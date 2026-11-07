# rmfit — agent-operable global R-matrix fitting on AZURE2

`rmfit` drives the in-process AZURE2 engine (`pyazr`) to do what an evaluator does by
hand, on a schedule a script can follow and an LLM agent can resume:

- **sharded evaluation** — the data segments are split across N single-thread engine
  sessions (chi-squared is additive over segments), so one objective or Jacobian of a
  35,000-point model costs seconds instead of tens of seconds;
- **bounded local polishes** in reduced-width-amplitude space with the analytic
  Jacobian (Wigner-limit bounds, energy windows, sign locks);
- **sign rounds** — canonical single/pair interference-sign flips per J-group, screened
  with one Gauss-Newton step, polished with the flipped sign locked, then merged one at a
  time and re-verified on a fresh full-model session;
- **structure rounds** — ATARI-style backward elimination and forward addition from a
  candidate bank with J^pi scans at pinned energies, holdout checks and outcome
  classification (accept / collapse / blowup / live-harmful / relocated / reverts);
- **energy-ladder continuation** for from-scratch fits;
- a **ledger** (SQLite + npz) of every candidate with provenance, and a `STATUS.md`
  a fresh session can read to continue a campaign.

Layout (design rationale and roadmap: `DESIGN.md` in this directory; the plan file the first campaign readme cites is gone):

| module | role |
|---|---|
| `keys.py` | structured parameter keys (energy, width, norm, shift, shift_sqrt, shift_fn, abundance, density, doppler, thickness, screening) and index maps between model variants; canonical sign patterns; `sign_distance` (minimal flips between two patterns modulo the gauge symmetries) |
| `model.py` | model variants written as new `.azr` files (shards, windows, with/without level) |
| `engine.py` | `SingleSession` (authoritative) and `Sharded` evaluators; `ObjectiveSpec` (plain chi2, reduced-chi2 per data set, Sivia loss) |
| `local.py` | bounded trust-region polishes, staged fits, sanity checks |
| `ledger.py` | candidate store, rounds, status |
| `moves.py` | physics-informed proposals |
| `search.py` | sign rounds, basin-crossover rounds, the shared screen/polish/union machinery |
| `structure.py` | level add / remove / dataset-off hypotheses |
| `windows.py` | energy-ladder driver |
| `levelscan.py` | residual-driven level search: candidate energies from residual runs, template screen of every J^pi x width partition x sign pattern at each (`rmfit levelscan`); relocation of an existing level with a narrow energy window (`rmfit relocate`) |
| `diagnose.py` | per-dataset tables, residual scans, runaway detection, figures |
| `cli.py` | `rmfit ...` subcommands |
| `enginepin.py` | the engine a campaign was started on (AZURE2_ROOT, `_azure2` .so md5, commit); refusal to run on another (2026-11-07) |
| `spec.py` | the fit specification `spec.json` / `SPEC.md`: data-set roles and norms, window, frozen block, bounds, pre-authorized actions, standing decisions; `rmfit spec check\|render\|derive`, `init --spec` (2026-11-07) |
| `decisions.py` | `DECISIONS.md`, the queue of questions outside the spec (`rmfit decisions`, `rmfit decide`); a level add the spec does not pre-authorize ends `accept-pending` with an entry here |
| `audit.py` | `rmfit audit`: engine-free pre-flight checks of the model and data -> `AUDIT.md` (zero free widths, 1 keV level merges, nominal norms != 1, normError as a fraction, FLAG columns as errors, tiny errors, duplicates, spikes, cross-file duplicates, thresholds, `<targetInt>` on test segments, legacy .sav names, output path, engine pin) |
| `covariance.py` | data covariance matrices (`covariance <file>`) and normalization groups (`normgroup <label>`): the engine's whitening redone on the evaluator's rows, the normgroup leader map (2026-10-22) |
| `mixture.py` | joint fit of several projects (one compound nucleus each) to data they share -- natural-abundance or compound targets: one worker per member, member-tagged keys, abundance weights (fixed or free with a sum-to-one row), one normalization per shared data set; `freeze_and_exchange` writes every member back as a standalone stage-1 file with the others as `mixture` tables (`python3 -m rmfit.mixture <dir> init|polish|freeze|status`) |

First campaign: `~/R-matrix/13C+a/9-5-26_rmfit_campaign/`.

Running: `rmfit` is not installed as a package; put its parent on the path:

    PYTHONPATH=/groups/rdeboer1/user/rdeboer1/R-matrix python3 -m rmfit.cli <campaign_dir> status

Tests (13N model): `python3 rmfit/tests/test_spine_13n.py`, `python3 rmfit/tests/test_search_13n.py`.  They
were seconds when written (2026-09-05); since the mid-September target-integration tolerance change a 13N
session opens in ~5 min and evaluates in ~8 s (about 100 sub-points per point, 370k external-capture
amplitudes), so the spine test's polish section now runs 1-2 h -- give it a long timeout or a quiet node.

Joint fits (`rmfit.mixture`): a directory with `mixture.json` naming the member projects
(`name`, `azr`, `flags`, `weight`, `weight_free`, `weight_sigma`) and the shared data sets
(`name`, `segments: {member: that member's <segmentsData> key}`); every member's file carries
the shared data as an ordinary segment (same data file, window and observable, its own
normalization free and 1).  The model of a shared data set is `sum_k w_k f_k`, its one
normalization applies to all members, and a member's energy shift of it stays at the file's
value.  Test (13N and the p+p model sharing a 90-degree elastic set, ~20 min):
`python3 rmfit/tests/test_mixture_13n_pp.py`.  First use: natural neon, `17O+a` (20Ne+n) with
`22Ne+n` and `21Ne+n` (2026-10-12, `17O+a/10-13-26_natNe_joint`).  Since 2026-10-13 the mixture feature
(engine, pyazr API) is not on AZURE2 `dev` but on `feature/multi-compound-nucleus`: run anything that
imports `rmfit.mixture` with `AZURE2_ROOT` pointing at a build of that branch AT COMMIT bc3bd57 (the last
one with the mixture pyazr API; the branch moved on to several compound nuclei in one project on
2026-10-13, which supersedes `rmfit.mixture`).  For that one-file feature, `keys.py` knows a parameter kind
`abundance` (`ParamKey.nucleus = (Z, A)`) and `Penalties.from_segments(keys, segs, azr)` adds the
`<abundances>` priors as rows (the sum-to-one term is not a row); on `dev`'s engine neither path is ever
taken.  Two 2026-10-13 regressions, both fixed the same day: `from_segments` was first called with
`self.azr` from `Sharded`, which only has `base_azr` (killed five sharded 13C+a jobs; `engine.py.bak-2026-10-13b`),
and `sign_distance` enumerated pair nodes without the stage-2 member tag (`KeyError` on every call;
`keys.py.bak-2026-10-13c`).  Any edit here must pass `tests/test_keys.py` (seconds) and a `Sharded` fixture
(`tests/test_levelscan_13n.py`, queue job template `tests/_queue_sharded/run_crc_sharded`) before it stays.

Level labels with several compound nuclei in one project (2026-10-30, report from the 17O+a session).  The engine
has one J-group per (J^pi, nucleus), each numbered from 1, so in a natural-target project with two odd-A nuclei
(21Ne and 23Ne in `17O+a/10-26-26_joint_ODeSA/an6pre.azr`) the plain label `"1/2-#2"` named two levels: before
this fix `level_energy` kept ONE energy per label (`default_bounds` then took width caps and floors, the background
test and the total-width floors from the other nucleus's level) and two free energies shared the key `E[1/2-#1]`.
Now every level label of a multi-nucleus model reads `"<J^pi>#<n>@<nucleus>"` (`"1/2-#2@21Ne"`; `keys.level_label`,
the nucleus from the pairs of the J-group's widths, `jgroup_nucleus_tags`); a single-nucleus model keeps the plain
label byte for byte, so ledgers and checkpoints are unchanged.  `ParamKey.ordinal` / `.jpi` / `.nucleus_tag` and
`keys.level_group` (`"1/2-@21Ne"`) parse it; the same-J^pi spacing checks (`local.py`), the backward-elimination
group count, `Campaign._level_energy` (active levels of that J^pi AND nucleus) and
`structure.deactivate_level_variant(nucleus=...)` use the nucleus; `build_keys` refuses duplicate energy/width
keys.  Still per J^pi only (conservative, frees or selects both nuclei's groups): the sign-round groups
(`moves.py`, `search.py`) and `free_mask(jpi=...)`.  Level ADD / levelscan variants are not multi-nucleus aware
(they pick pairs 1 and 2).  Test `tests/test_level_labels_multicn.py` (fixture `tests/fixtures/multicn_labels`,
13N + 15N; Single and Sharded, ~10 s); backups `*.bak-2026-10-30-cnlabel`.

Data covariances, normalization and shift groups (2026-10-22, `covariance.py`).  AZURE2's segment keywords
`covariance <file>` (dev 4b71177), `normgroup <label>` (dev 3e13fb2) and `shiftgroup <label>` work in both evaluators:

- Workers never see `covariance`: `SingleSession` runs a sibling `<model>.nocov.azr`, shard files drop it,
  and the evaluator whitens the assembled data rows with the engine's own algorithm (same rows in file-row
  order, same D = sqrt(C_ii), same B components, V and T; `W = (I + V T V^T) L_B^-1`), so the rows equal
  the engine's `residual_jacobian` rows to rounding and a group split across shards keeps its correlations.
  `SingleSession` compares its chi2 with an engine session on the model as written at its FIRST
  evaluation and stops on a mismatch (RMFIT_COV_CHECK=0 skips it) -- which is also what happens with a
  pyazr built before 4b71177, whose engine ignores the keyword.
- `relvector` terms: the model is frozen at the evaluator's first evaluation (as the engine freezes at a
  run's first evaluation); `ev.refreeze_covariance()` re-freezes at the next one.  Each `rmfit` CLI step is
  a new process, so every polish starts from a model frozen at its own starting point (Chiba-Smith).
- Row weights (`dataset_weight`, `point_weights`) act on the plain rows BEFORE whitening (inflated
  errors, correlations kept); the Sivia loss is refused on covariance rows.  `rows_chi2(r)` is the plain
  chi2; `point_chi2(r)` gives each row's share `r_i (M^-1 r)_i` (adds up to chi2; levelscan/diagnose use
  it), `point_residuals(r)` the plain normalized residuals before whitening.  Per-segment chi2 are the
  engine's partition shares (can be negative).
- `normgroup`: single sessions leave it to the engine (the worker's one-evaluation residuals now use the
  leader's norm for a follower); shard files drop it, a follower's pieces run at their own fixed norm `n0`
  and `Sharded` rescales them to the leader's `n`: `r = (n0/n)(r0 + q) - q`, `q = d/sigma`.
- Keep covariance files under `data/`.  Shards need none (the evaluator reads it from the base model's
  directory) and `single_variant` links one that sits next to the model, but the structure, window and
  levelscan variants link only `data/`.
- `shiftgroup`: every member follows the constant shift of the group's first active segment, so `build_shards`
  puts all pieces of a group into ONE shard, which keeps the keyword (exact there; a finite-difference step of
  the group's shift moves every member).  A group with a free shift is one shift-solo unit.
- `shiftfngroup` (AZURE2 dev 62392fc; rmfit 2026-10-24): every member uses the shift function of the group's first
  active member, which declares it, so a group's pieces go to ONE shard (as a shiftgroup) and no member is ever split
  (a split owner would declare the function twice).  Shard files keep file order, so the owner stays first.  Test
  tests/test_shiftfngroup_sharded.py (fixture tests/fixtures/shift_fn_groups; needs AZURE2_ROOT at a >= 62392fc build).
- Free `sqrtshift` coefficients and `shiftfn` parameters (2026-10-22; before, `build_keys` raised "unknown parameter
  kind" and rmfit could not open such a model): keys `('shift_sqrt', seg)` and `('shift_fn', seg, term=j)`, the
  engine's penalties as rows (`Penalties.from_segments`, equal to pyazr's `penalties()`), bounds and `free_mask`
  like constant shifts (`BoundsPolicy.shifts_free`, `shift_nsigma`); a segment with any free shift term is never
  split and counts as shifted for the shift-solo shards.
- Held finite-difference columns are not computed (2026-10-30, DeBoer "go ahead with the column mask"): the engine
  finite-differences every free shift, sqrt(E)-shift, shift-function and density column (two evaluations each), also
  the ones polish's bounds hold.  `Evaluator.residuals(x, jac=True, cols=...)` now names the columns the caller reads;
  the workers skip the others (pyazr `residual_jacobian(skip=)`, AZURE2 dev 753c6f0 or later), which come back zero
  on the data rows.  `polish` asks for its free columns, `gn_step` for its own.  Older pyazr builds compute every
  column as before.  Before this, a 17O+a an6pre polish with 8 held shift terms spent ~16 of ~18 evaluations per
  Jacobian on columns it discarded (7.5 h without a finished Jacobian).  Test tests/test_jac_skip_columns.py.
- Fitted target densities (`densityfit` / `densitygroup` on a `<targetInt>` line; AZURE2 branch
  dev f272a35, 2026-10-29): key `density[t<n>]` (`ParamKey.effect` = the
  line's effect number, a group's first line), its prior as a row read from the base .azr
  (`AzrModel.target_densities`), bounds [0.01 N0, max] in `default_bounds` (`SingleSession.density_info`).
  SingleSession only: `build_keys` raises for a shard (whether a shard keeps every `<targetInt>` line is untested).
  The density is in atoms/cm^2 (~1e17): `polish`'s `x_scale="jac"` handles the scale.
- Fitted Doppler temperatures and sample thicknesses (AZURE2 2026-11-05: `doppler T vary sigma [Tmax]` on a
  `<targetInt>` line; `transmission|yield n vary sigma` and `thicknessgroup` on a segment line): keys `doppler[t<n>]`
  (`ParamKey.effect`, as a density) and `thickness[seg<k>]` (`ParamKey.seg`; a thicknessgroup follower has no free
  parameter, so only the leader's key appears). Priors as rows read from the base .azr (`AzrModel.dopplers`,
  `AzrModel.sample_thicknesses`); bounds in `default_bounds`: T in [T0/4, the layout temperature], n in
  [1e-6 n0, inf) (`SingleSession.doppler_info` / `thickness_info`). SingleSession only: `build_keys` raises for a shard
  (a split transmission segment and a thicknessgroup across shards are not designed). The fitted values travel in
  the .sav (pyazr `save_fit`), the .azr keeps the prior centres. Needs a pyazr that knows kinds 9 and 10.
  Test tests/test_doppler_thickness_kinds.py.
- Electron-screening potentials (`screening Ue vary sigma` on a `<targetInt>` line; AZURE2 dev since 2026-10): key
  `screening[t<n>]` (`ParamKey.effect`), its prior as a row from `AzrModel.screenings`, bounds [0, inf) as the
  engine's. SingleSession only. Until 2026-11-05 `build_keys` stopped at this kind. Test tests/test_screening_kind.py.
- levelscan equal-split sign templates (`_patterns`): until 2026-11-06 all 2^n sign vectors were listed before
  `--max-signs` of them were sampled, so any J^pi with >= ~30 open channels was OOM-killed (300-650 GB at n = 30-31;
  10B+a step 4 3- at 14.63 MeV, step 5 2+/3- at 15.27 MeV). Now the same indices are drawn from 2^n and decoded:
  identical templates, bounded memory. Test tests/test_patterns_signs_memory.py.
- Conv pieces are made only for segments without any energy shift: until 2026-10-22 a fixed nonzero shift,
  a `sqrtshift`, `shiftfn` or a shift group's shift was silently dropped on the conv grid line.

Tests: `13C+a/10-22-26_rmfit_covariance/tests/` (`test_covariance_rmfit.py`: rows and Jacobian = the engine's,
Single = Sharded, gradients, refreeze, weights, bake; the old/new bit-identity dumps; the ND2021r scale run).

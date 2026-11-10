#!/usr/bin/env python3
"""Benchmark suite (DESIGN.md Phase 3.1).

A case (``cases/<name>.json``) names a REFERENCE campaign (a finished, human-judged fit re-measured on the pinned engine; with
``reference.polish_rounds`` > 0 the job first polishes it to convergence, for a reference that is only a start file) and
RUNS (campaigns the drive produced from a degraded start of that reference).  ``score`` reads the ledgers only (no engine):

    objective          incumbent objective of the run and of the reference
    data chi2          sum of the per-data-set chi2 of the incumbent (ledger segment scores); penalty = objective - data chi2
    sign distance      keys.sign_distance between the two incumbents (same structure only)
    wait decisions     DECISIONS.md entries with default 'wait' (the ones that stop a run); human turns = answered by a person
    node hours         drive_state.json wall_hours (one node), with the slot count
    new review flags   HIGH/MEDIUM findings of the run's REVIEW.md that the reference's REVIEW.md does not have

and applies the recovery yardstick adopted 2026-11-09:  PASS = data chi2 <= reference's, objective within 0.5 %, zero wait
decisions, no new HIGH/MEDIUM review flag; EXACT (secondary) = objective within 1e-4.  Rows go to ``results.tsv``.

``run`` writes the SGE job for one run from the case's ``reference`` and the run's ``start`` and ``spec`` entries (reference
init if missing, ``rmfit perturb``, spec copied, ``rmfit drive`` to DONE / WAITING / STOP), modelled on the 7Be benchmark's
run_crc_bench4; ``--submit`` queues it (needs a Kerberos ticket: see the crc-cluster-jobs skill)."""
import argparse, json, os, re, subprocess, sys, time
from typing import Dict, List, Optional

HERE = os.path.dirname(os.path.abspath(__file__))
RESULTS = os.path.join(HERE, "results.tsv")
COLUMNS = ["date", "case", "tier", "run", "label", "status", "reference_objective", "objective", "objective_rel_pct", "data_chi2",
           "data_chi2_ref", "penalty", "penalty_ref", "sign_distance", "wait_decisions", "human_turns", "node_hours", "slots",
           "new_flags", "pass_data", "pass_objective", "pass_decisions", "pass_flags", "verdict", "exact_1e-4", "note"]
YARD = dict(objective_rel_max=0.005, exact_rel=1e-4)

_FLAG_RE = re.compile(r"^- \*\*(HIGH|MEDIUM|LOW|INFO)\*\* `([^`]+)`: ([^:]*)")


def load_case(path: str) -> dict:
    case = json.load(open(path))
    case["_path"] = os.path.abspath(path)
    base = case.get("base_dir") or os.path.dirname(case["_path"])
    if not os.path.isabs(base):
        base = os.path.normpath(os.path.join(os.path.dirname(case["_path"]), base))
    case["_base"] = base
    return case


def review_flags(campaign_dir: str) -> Optional[set]:
    """(severity, code, subject) of every HIGH/MEDIUM finding in <dir>/REVIEW.md; None when there is no review."""
    path = os.path.join(campaign_dir, "REVIEW.md")
    if not os.path.exists(path):
        return None
    out = set()
    for line in open(path):
        m = _FLAG_RE.match(line.strip())
        if m and m.group(1) in ("HIGH", "MEDIUM"):
            out.add((m.group(1), m.group(2), m.group(3).strip()))
    return out


def _campaign(d):
    sys.path.insert(0, os.path.dirname(os.path.dirname(HERE)))
    from rmfit.campaign import Campaign
    return Campaign(d, enforce_engine=False)      # ledgers only; a review (--review) runs on whatever engine is imported (noted)


def incumbent_split(c) -> dict:
    cid, x, obj, keys = c.incumbent()
    tab = c.dataset_table(cid)
    data = sum(float(d["chi2"]) for d in tab)
    return dict(cid=cid, x=x, objective=float(obj), keys=keys, data_chi2=data, penalty=float(obj) - data, table=tab)


def decisions_summary(run_dir: str) -> dict:
    from rmfit.decisions import DecisionQueue as Decisions
    path = os.path.join(run_dir, "DECISIONS.md")
    if not os.path.exists(path):
        return dict(wait=0, human=0, n=0)
    ds = Decisions(path).all()
    wait = sum(1 for d in ds if (d.get("default_if_unanswered") or "wait").strip() == "wait")
    human = sum(1 for d in ds if d.get("answer") and (d.get("answered_by") or "").strip() not in ("", "default", "rmfit drive", "test"))
    return dict(wait=wait, human=human, n=len(ds))


def score_run(case: dict, run_name: str, review_missing: bool = False) -> dict:
    ref_dir = os.path.join(case["_base"], case["reference"]["campaign"])
    run = case["runs"][run_name]
    run_dir = os.path.join(case["_base"], run["dir"])
    r, p = _campaign(ref_dir), _campaign(run_dir)
    R, P = incumbent_split(r), incumbent_split(p)
    row: Dict[str, object] = dict(date=time.strftime("%Y-%m-%d"), case=case["name"], tier=case.get("tier", ""), run=run_name,
                                  label=run.get("label", ""), reference_objective=round(R["objective"], 3), objective=round(P["objective"], 3),
                                  data_chi2=round(P["data_chi2"], 1), data_chi2_ref=round(R["data_chi2"], 1),
                                  penalty=round(P["penalty"], 1), penalty_ref=round(R["penalty"], 1))
    rel = P["objective"] / R["objective"] - 1.0
    row["objective_rel_pct"] = round(100 * rel, 3)
    # sign distance (same structure only)
    try:
        from rmfit.keys import take, sign_distance
        if [str(k) for k in R["keys"]] == [str(k) for k in P["keys"]]:
            dist, _ = sign_distance(P["x"], R["x"], P["keys"], p.ledger.fixed_of(p.structure_id))
            row["sign_distance"] = int(dist)
        else:
            xr = take(R["x"], R["keys"], P["keys"], P["x"])
            dist, _ = sign_distance(P["x"], xr, P["keys"], p.ledger.fixed_of(p.structure_id))
            row["sign_distance"] = f"{int(dist)} (key sets differ)"
    except Exception as err:  # noqa: BLE001
        row["sign_distance"] = f"n/a ({err})"
    dec = decisions_summary(run_dir)
    row["wait_decisions"], row["human_turns"] = dec["wait"], dec["human"]
    st_path = os.path.join(run_dir, "drive_state.json")
    st = json.load(open(st_path)) if os.path.exists(st_path) else {}
    row["status"] = f"{st.get('status', '?')}@{st.get('state', '?')} cycle {st.get('cycle', '?')}" if st else "no drive_state.json"
    row["node_hours"] = round(float(st.get("wall_hours", 0.0)), 2) if st else ""
    row["slots"] = p.cfg.get("nshards", "")
    # review flags
    stale = []
    for c, I in ((r, R), (p, P)):
        rv = os.path.join(c.dir, "REVIEW.md")
        have = _review_cid(rv)
        if (not os.path.exists(rv) or (have is not None and have != int(I["cid"]))):
            if review_missing:
                from rmfit.review import review_campaign
                from rmfit import enginepin
                cur, pin = enginepin.fingerprint(), c.cfg.get("engine") or {}
                review_campaign(c, grid_check=False, figures=0)
                if pin.get("so_md5") and pin["so_md5"] != cur.get("so_md5"):
                    stale.append(f"{os.path.basename(c.dir)} reviewed on engine {enginepin.short(cur)} (pinned {enginepin.short(pin)})")
            elif os.path.exists(rv):
                stale.append(f"{os.path.basename(c.dir)} REVIEW.md is of candidate {have}, incumbent {I['cid']}")
    fr, fp = review_flags(ref_dir), review_flags(run_dir)
    if stale:
        row["note"] = "; ".join(stale)
    if fr is None or fp is None:
        row["new_flags"] = "n/a (no REVIEW.md in " + ", ".join(n for n, f in (("reference", fr), ("run", fp)) if f is None) + ")"
        pass_flags = None
    else:
        new = sorted(fp - fr)
        row["new_flags"] = "; ".join(f"{s} {c} {n}" for s, c, n in new) if new else "none"
        pass_flags = not new
    row["pass_data"] = P["data_chi2"] <= R["data_chi2"] * (1 + 1e-9)
    row["pass_objective"] = rel <= YARD["objective_rel_max"]
    row["pass_decisions"] = dec["wait"] == 0
    row["pass_flags"] = "n/a" if pass_flags is None else pass_flags
    ok = row["pass_data"] and row["pass_objective"] and row["pass_decisions"] and (pass_flags is not False)
    row["verdict"] = "PASS" if ok else "FAIL"
    row["exact_1e-4"] = abs(rel) <= YARD["exact_rel"]
    if rel < -0.01:
        # a run that beats the reference by more than 1 % says the REFERENCE is not a converged fit on this engine / objective
        # (13N tier 0, 2026-11-09: the fixture's .azr holds start values, its fit lives in param.par): the row is not a recovery score
        row["verdict"] = "REFERENCE-SUSPECT"
        stale.append(f"run beats the reference by {-100 * rel:.1f} %: the reference is not a converged fit; rebuild it")
    row["note"] = "; ".join(t for t in (run.get("note", ""), row.get("note", ""), "; ".join(stale[1:] if row.get("note") else stale)) if t)
    return row


def _review_cid(path: str) -> Optional[int]:
    """The candidate a REVIEW.md was written for (its header line), or None."""
    if not os.path.exists(path):
        return None
    for line in open(path):
        m = re.search(r"incumbent candidate (\d+)", line)
        if m:
            return int(m.group(1))
    return None


def append_rows(rows: List[dict]):
    new = not os.path.exists(RESULTS)
    with open(RESULTS, "a") as fh:
        if new:
            fh.write("\t".join(COLUMNS) + "\n")
        for row in rows:
            fh.write("\t".join(str(row.get(c, "")).replace("\t", " ") for c in COLUMNS) + "\n")


def print_rows(rows: List[dict]):
    for row in rows:
        print(f"{row['case']} / {row['run']} ({row['label']}): {row['verdict']}  objective {row['objective']} vs {row['reference_objective']} "
              f"({row['objective_rel_pct']:+} %), data chi2 {row['data_chi2']} vs {row['data_chi2_ref']}, penalty {row['penalty']} vs {row['penalty_ref']}, "
              f"sign distance {row['sign_distance']}, wait decisions {row['wait_decisions']}, human turns {row['human_turns']}, "
              f"{row['node_hours']} node-hours on {row['slots']} slots, new flags: {row['new_flags']}; exact {row['exact_1e-4']}; {row['status']}")


JOB = """#!/bin/csh
#$ -M {email}
#$ -m a
#$ -q long
#$ -pe smp {slots}
#$ -N {jobname}
#$ -cwd
#$ -j y
#$ -o {log}
# rmfit bench (DESIGN.md Phase 3.1): case {case} run {run} -- {label}
# reference campaign {refdir} from {refazr}; start = `rmfit perturb` ({flips} flips, seed {seed}, jitter {jitter}, ekick {ekick},
# polished {pnfev}); spec {spec}; then `rmfit drive` to DONE / WAITING / STOP.  Score afterwards with
#   python3 -m rmfit.bench score {casefile} {run}
source ${{HOME}}/.login
module load gsl/gcc/2.8
module unload python
setenv PATH /software/p/python/3.12.15/gcc/11.5.0/bin:${{PATH}}
setenv LD_LIBRARY_PATH /software/s/sqlite-libs/3.34.1-11.el9_8/usr/lib64:/software/p/python/3.12.15/gcc/11.5.0/lib:${{LD_LIBRARY_PATH}}
setenv AZURE2_ROOT {azure2_root}
setenv PYTHONPATH {rmatrix}:${{AZURE2_ROOT}}
setenv OMP_NUM_THREADS 1
setenv PYTHONUNBUFFERED 1
cd {base}
echo "host `hostname` `date` job $JOB_ID"
python3 -c "import rmfit, rmfit.drive, pyazr; print('imports', pyazr.__file__, rmfit.__file__)"
if ($status != 0) exit 1
set RM = "python3 -m rmfit.cli"
if (! -e {refdir}/campaign.json) then
  echo "`date` reference init"
  $RM {refdir} init --base {refazr} {savarg} --nshards {nshards} {flagsarg} {policyarg} {searcharg} --note "bench {case} reference"
  if ($status != 0) then
    echo "`date` reference init FAILED"; exit 1
  endif
endif
{polish}if (! -e {rundir}/campaign.json) then
{startblock}endif
if (! -e {rundir}/spec.json) cp {spec} {rundir}/spec.json
{searchpatch}
echo "`date` drive"
$RM {rundir} drive --max-minutes 0
echo "`date` drive exit $status"
$RM {rundir} drive --dry-run
echo "`date` all done"
"""


def write_job(case: dict, run_name: str) -> str:
    import getpass
    ref, run = case["reference"], case["runs"][run_name]
    base = case["_base"]
    start = dict(dict(flips=8, seed=0, jitter=0.0, ekick=0.0, polish_nfev=300), **(run.get("start") or {}))

    def jarg(flag, key):
        v = ref.get(key)
        return f"{flag} @{v}" if v else ""
    spec = run.get("spec") or ""
    if not spec:
        raise SystemExit(f"run {run_name} has no 'spec' (path of the drive spec, relative to the case's base_dir)")
    polish = ""
    if int(ref.get("polish_rounds") or 0) > 0:
        # a reference that is not a converged fit (a start file, a regression fixture) is polished to convergence first;
        # the marker file keeps a resubmitted job from polishing it again
        polish = (f"if (! -e {ref['campaign']}/.bench_polished) then\n"
                  f"  echo \"`date` reference polish ({ref['polish_rounds']} rounds of {ref.get('polish_nfev', 300)})\"\n"
                  f"  foreach i (`seq 1 {int(ref['polish_rounds'])}`)\n"
                  f"    $RM {ref['campaign']} polish --nfev {int(ref.get('polish_nfev') or 300)} --tighten\n"
                  f"  end\n"
                  f"  touch {ref['campaign']}/.bench_polished\n"
                  f"endif\n")
    if start.get("azr"):
        # a degraded start that is a FILE (the archived state before the human's key decision), not a random perturbation
        # of the reference: the run campaign is initialised on it with the reference's engine settings
        startblock = (f"  echo \"`date` start from {start['azr']}\"\n"
                      f"  $RM {run['dir']} init --base {start['azr']} {('--sav ' + start['sav']) if start.get('sav') else ''} "
                      f"--nshards {int(ref.get('nshards') or 8)} {jarg('--flags', 'flags')} {jarg('--policy', 'policy')} {jarg('--search', 'search')} "
                      f"--note \"bench {case['name']} start {start['azr']}\"\n"
                      f"  if ($status != 0) then\n    echo \"`date` start init FAILED\"; exit 1\n  endif\n")
    else:
        startblock = (f"  echo \"`date` perturb\"\n"
                      f"  $RM {ref['campaign']} perturb --out {run['dir']} --flips {start['flips']} --seed {start['seed']} --jitter {start['jitter']} "
                      f"--ekick {start['ekick']} --polish-nfev {start['polish_nfev']}\n"
                      f"  if ($status != 0) then\n    echo \"`date` perturb FAILED\"; exit 1\n  endif\n")
    searchpatch = ""
    if run.get("search"):
        searchpatch = (f"python3 -c \"import json; c=json.load(open('{run['dir']}/campaign.json')); c['search']=json.load(open('{run['search']}')); "
                       f"json.dump(c, open('{run['dir']}/campaign.json','w'), indent=2); print('search ->', c['search'])\"")
    email = f"{getpass.getuser()}@nd.edu"
    rmatrix = os.path.dirname(os.path.dirname(HERE))
    text = JOB.format(email=email, slots=int(run.get("slots") or ref.get("nshards") or 8), jobname=f"bench_{case['name']}_{run_name}"[:40],
                      log=f"bench_{run_name}.log", case=case["name"], run=run_name, label=run.get("label", ""), refdir=ref["campaign"],
                      refazr=ref["azr"], flips=start["flips"], seed=start["seed"], jitter=start["jitter"], ekick=start["ekick"],
                      pnfev=start["polish_nfev"], spec=spec, casefile=case["_path"], azure2_root=ref.get("azure2_root") or os.path.expanduser("~/AZURE2"),
                      rmatrix=rmatrix, base=base, savarg=(f"--sav {ref['sav']}" if ref.get("sav") else ""), nshards=int(ref.get("nshards") or 8),
                      flagsarg=jarg("--flags", "flags"), policyarg=jarg("--policy", "policy"), searcharg=jarg("--search", "search"),
                      rundir=run["dir"], searchpatch=searchpatch, polish=polish, startblock=startblock)
    path = os.path.join(base, f"run_crc_bench_{run_name}")
    with open(path, "w") as fh:
        fh.write(text)
    os.chmod(path, 0o755)
    return path


def main(argv=None):
    ap = argparse.ArgumentParser(prog="python3 -m rmfit.bench", description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    sub = ap.add_subparsers(dest="cmd", required=True)
    p = sub.add_parser("score", help="score finished runs of a case against its reference; append rows to results.tsv")
    p.add_argument("case")
    p.add_argument("runs", nargs="*", help="run names (default: every run of the case that has a ledger)")
    p.add_argument("--review", action="store_true", help="write a REVIEW.md (engine, ~1 min per campaign) where one is missing")
    p.add_argument("--no-append", action="store_true", help="print only; do not touch results.tsv")
    p = sub.add_parser("run", help="write the SGE job for one run (reference init, perturb, spec, drive)")
    p.add_argument("case")
    p.add_argument("run")
    p.add_argument("--submit", action="store_true")
    p = sub.add_parser("list", help="cases and their runs")
    p.add_argument("case", nargs="?")
    a = ap.parse_args(argv)
    if a.cmd == "list":
        files = [a.case] if a.case else sorted(os.path.join(HERE, "cases", f) for f in os.listdir(os.path.join(HERE, "cases")) if f.endswith(".json"))
        for f in files:
            c = load_case(f)
            print(f"{c['name']} (tier {c.get('tier')}, {c.get('reaction')}): reference {c['reference']['campaign']}; runs: "
                  + ", ".join(f"{k} [{v.get('label', '')}]" for k, v in c["runs"].items()))
        return
    case = load_case(a.case)
    if a.cmd == "run":
        path = write_job(case, a.run)
        print("job script:", path)
        if a.submit:
            out = subprocess.run(["qsub", os.path.basename(path)], cwd=case["_base"], capture_output=True, text=True)
            print(out.stdout.strip(), out.stderr.strip())
        return
    runs = a.runs or [k for k, v in case["runs"].items() if os.path.exists(os.path.join(case["_base"], v["dir"], "ledger.sqlite"))]
    rows = [score_run(case, r, review_missing=a.review) for r in runs]
    print_rows(rows)
    if not a.no_append:
        append_rows(rows)
        print("appended to", RESULTS)


if __name__ == "__main__":
    main()

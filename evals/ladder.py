#!/usr/bin/env python
"""ladder.py - score one skill run against the corpus ladder, and regenerate
evals/ladder.md (docs/design.md section 3, "### M6.").

    ladder.py --skill vde --rung uart --run WS --hand-edits N [--rulings R]
              [--session-tokens T] [--session-cost-usd C] [--wall-s S]
              [--note TEXT] [--reference]
    ladder.py --regen

It scores a run a session already made; it never drives an agent. From the
run's workspace it records whether every gate went green (attest.py's own
check: every gate the skill owes has a fresh pass or a bound waiver, no
open issue, plus a fresh `release` pass), then runs the corpus's own
held-out tests, which the run never saw, on a copy of the workspace: the
strong form of docs/design.md section 2. Beside those it records the kill
rate, area and worst slack from the gates' recorded facts, the fix attempts
(gate attempts past the first), the tokens and cost from the spawn ledger
plus the orchestrating session's own, and the wall time.

Hand edits cannot be read off a workspace, so the caller declares them with
`--hand-edits`; it is required. A rung COUNTS when every gate is green, the
held-out tests pass, and there were no hand edits.

Rulings are not hand edits. A ruling is the owner's answer on one mutation
survivor in a workspace's spec/mutant_rulings.yaml (engine/lib/rulingslib.py),
a documented human channel like an H-gate answer, so it is scored as its own
field and does not stop a rung counting. The score counts the entries in
every spec/mutant_rulings.yaml under the run (a /msde run nests one per side)
and the caller declares with `--rulings` (default 0) how many of them the
owner wrote. Nothing stops the run under test writing that file itself - the
skills only say no agent may - so an entry beyond the declared count is
scored as an undeclared ruling and stops the rung like a hand edit;
declaring more than the file holds is an error.

`--reference` marks a run that is not a skill session (the corpus reference
RTL with its gates run by gate.py, say). Its result is kept, but ladder.md
lists it under "Reference baselines" and never on the skill's column, which
shows only skill runs.

Every scored run is a dated JSON under evals/results/ladder/. ladder.md is
rebuilt from the newest result per rung, the bench baselines under
evals/fixtures/, and the newest full-subset CVDP result under evals/results/cvdp/
(the pinned non-agentic file, no --category, no --limit, every subset problem
selected; the newest other run, labelled as such, when there is none), so the
ade and msde columns fill in as their results land. Exit 0 the rung counts,
1 it does not (the findings say why), 2 error; `--regen` exits 0.
"""
from __future__ import annotations

import argparse
import datetime as dt
import json
import shutil
import sys
import tempfile
from pathlib import Path

EVALS = Path(__file__).resolve().parent
REPO = EVALS.parent
ENGINE = REPO / "engine"
sys.path.insert(0, str(ENGINE / "scripts"))
sys.path.insert(0, str(ENGINE / "lib"))
import attest  # noqa: E402
import checklib  # noqa: E402
import gate as gate_mod  # noqa: E402
import rulingslib  # noqa: E402
import statelib  # noqa: E402
from checklib import CheckError  # noqa: E402

SCRIPT = "ladder"
CORPUS = REPO / "corpus"
RESULTS = EVALS / "results"
SKIP_COPY = {"runs", "state_snapshots", "log", "__pycache__"}
# evals/cvdp/run.py DATASETS["nonagentic"]["file"]: the benchmark the page reports
CVDP_PINNED_FILE = "cvdp_v1.1.0_nonagentic_code_generation_no_commercial.jsonl"


def load_ladder() -> dict:
    import yaml
    return yaml.safe_load((EVALS / "ladder.yaml").read_text(encoding="utf-8"))


def _ts(s: str | None):
    try:
        return dt.datetime.fromisoformat(s.replace("Z", "+00:00")) if s else None
    except ValueError:
        return None


def gates_green(ws: Path, data: dict) -> list[str]:
    """Why the run is not all-green; empty when it is."""
    _body, problems = attest.build(ws)
    fresh = statelib.freshness_report(data, ws).get("gates", {})
    rel = (data.get("gates") or {}).get("release") or {}
    if rel.get("status") != "pass":
        problems.append("release: no recorded pass")
    elif not (fresh.get("release") or {}).get("fresh"):
        problems.append("release: its pass is stale")
    return problems


def run_holdout(ws: Path, skill: str, rung_dir: Path) -> dict:
    """The corpus's held-out tests on a copy of the run's workspace."""
    rows = gate_mod.load_gates(gate_mod.DEFAULT_GATES).get(skill) or {}
    if "holdout" not in rows:
        return {"status": "n/a", "why": f"{skill} has no holdout gate"}
    src = rung_dir / "holdout"
    if not src.is_dir():
        raise CheckError(f"corpus rung {rung_dir.name} has no holdout/")
    with tempfile.TemporaryDirectory(prefix="chip-flow-ladder-") as tmp:
        copy = Path(tmp) / ws.name
        shutil.copytree(ws, copy, ignore=lambda d, names: [
            n for n in names if n in SKIP_COPY])
        if (copy / "holdout").exists():
            shutil.rmtree(copy / "holdout")
        shutil.copytree(src, copy / "holdout")
        try:
            report = gate_mod.run_report_for_gate(rows["holdout"], copy)
        except Exception as exc:  # noqa: BLE001  a gate that did not run
            raise CheckError(f"the held-out tests could not run: {exc}") from exc
        result = gate_mod.evaluate("holdout", rows["holdout"], report)
    return {"status": result["status"],
            "tests_passed": report.get("tests_passed"),
            "tests_run": len(report.get("tests_run") or []),
            "kinds": sorted({v.get("kind") for v in result.get("failing", [])
                             if v.get("kind")})}


def count_rulings(ws: Path) -> int:
    """Entries across every spec/mutant_rulings.yaml under the run."""
    import yaml
    n = 0
    for f in sorted(ws.rglob(rulingslib.RULINGS_REL)):
        if SKIP_COPY & set(f.relative_to(ws).parts):
            continue
        try:
            data = yaml.safe_load(f.read_text(encoding="utf-8"))
        except yaml.YAMLError as exc:
            raise CheckError(f"{f.relative_to(ws)} is not valid YAML: {exc}") from exc
        if data is None:
            continue
        if not isinstance(data, dict):
            raise CheckError(f"{f.relative_to(ws)} is not a YAML mapping")
        for key, entries in data.items():
            if key not in rulingslib.FIELDS or not isinstance(entries, (list, type(None))):
                raise CheckError(f"{f.relative_to(ws)}: unexpected {key!r} "
                                 "(see engine/lib/rulingslib.py)")
            n += len(entries or [])
    return n


def facts(data: dict, gate: str) -> dict:
    return ((data.get("gates") or {}).get(gate, {}).get("last") or {}).get("facts") or {}


def worst_slack(corners) -> float | None:
    vals = [c.get("setup_ws") for c in (corners or {}).values()
            if isinstance(c, dict) and isinstance(c.get("setup_ws"), (int, float))]
    return min(vals) if vals else None


def score(args) -> tuple[dict, list[dict]]:
    ws = Path(args.run).resolve()
    rung_dir = CORPUS / args.skill / args.rung
    if not rung_dir.is_dir():
        raise CheckError(f"no corpus rung at corpus/{args.skill}/{args.rung}")
    data = checklib.load_json(ws / "state.json", "run state.json")
    if data.get("skill") != args.skill:
        raise CheckError(f"the run is a {data.get('skill')!r} workspace, not {args.skill!r}")

    found = count_rulings(ws)
    if args.rulings < 0 or args.rulings > found:
        raise CheckError(f"--rulings {args.rulings} declared, but the run's "
                         f"{rulingslib.RULINGS_REL} files hold {found} entries")
    # brief: a ruling "does not stop the rung counting", but the run's own
    # writes to the rulings file are counted "as hand edits"
    undeclared = found - args.rulings
    green_problems = gates_green(ws, data)
    held = run_holdout(ws, args.skill, rung_dir)
    gates = data.get("gates") or {}
    spawns = data.get("spawns") or []
    tokens = sum(int(s.get("tokens") or 0) for s in spawns) + (args.session_tokens or 0)
    cost = sum(float(s.get("cost_usd") or 0) for s in spawns) + (args.session_cost_usd or 0)
    hist = [_ts(h.get("ts")) for h in data.get("history") or []]
    hist = [h for h in hist if h]
    wall = args.wall_s if args.wall_s is not None else (
        (max(hist) - min(hist)).total_seconds() if len(hist) > 1 else None)

    counts = (not green_problems and held["status"] in ("pass", "n/a")
              and args.hand_edits == 0 and undeclared == 0)
    result = {
        "skill": args.skill, "rung": args.rung, "block": data.get("block"),
        "run": ws.name, "phase": data.get("phase"),
        "scored_at": dt.datetime.now(dt.timezone.utc).isoformat(timespec="seconds"),
        "counts": counts,
        "gates_green": not green_problems,
        "gate_problems": green_problems,
        "gates_passed": sorted(g for g, e in gates.items() if e.get("status") == "pass"),
        "hand_edits": args.hand_edits,
        "rulings": args.rulings,
        "rulings_undeclared": undeclared,
        "held_out": held,
        "kill_rate": facts(data, "mutate").get("kill_rate"),
        "line_pct": facts(data, "cover").get("line_pct"),
        "area": facts(data, "synth").get("area"),
        "worst_slack_ns": worst_slack(facts(data, "timing").get("corners")),
        "fix_attempts": sum(max(0, int(e.get("attempts") or 0) - 1)
                            for e in gates.values()),
        "tokens": tokens or None,
        "cost_usd": round(cost, 2) if cost else None,
        "wall_s": round(wall) if wall is not None else None,
        "note": args.note,
        "kind": "reference" if args.reference else "skill",
    }
    violations = [checklib.violation("ladder", "error", None, args.rung,
                                     "gate_not_green", [], p, "attest")
                  for p in green_problems]
    if held["status"] == "fail":
        violations.append(checklib.violation(
            "ladder", "error", "holdout", args.rung, "holdout_failed", [],
            f"the corpus held-out tests fail ({', '.join(held['kinds'])})", "holdout"))
    if args.hand_edits:
        violations.append(checklib.violation(
            "ladder", "error", None, args.rung, "hand_edits", [],
            f"{args.hand_edits} hand edit(s) declared", "caller"))
    if undeclared:
        violations.append(checklib.violation(
            "ladder", "error", None, args.rung, "rulings_undeclared", [],
            f"{undeclared} mutant ruling(s) in the run that the caller did not "
            "declare as the owner's (--rulings): scored as hand edits", "caller"))
    return result, violations


# ---- ladder.md -------------------------------------------------------------

def latest(dirpath: Path, pattern: str) -> Path | None:
    files = sorted(dirpath.glob(pattern)) if dirpath.is_dir() else []
    return files[-1] if files else None


def is_full_cvdp(c: dict) -> bool:
    """A full-subset run: the pinned benchmark file, no --category, no
    --limit, every subset problem selected. A smoke, category or example
    (positive-control) run must not stand in for the number the page reports."""
    return ((c.get("dataset") or {}).get("file") == CVDP_PINNED_FILE
            and c.get("categories") is None and c.get("limit") is None
            and c.get("selected") is not None
            and c.get("selected") == c.get("subset_size"))


def latest_cvdp(dirpath: Path) -> Path | None:
    """The newest full-subset CVDP run, else the newest run of any kind."""
    files = sorted(dirpath.glob("*.json")) if dirpath.is_dir() else []
    full = [f for f in files
            if is_full_cvdp(json.loads(f.read_text(encoding="utf-8")))]
    return (full or files or [None])[-1]


def latest_ladder_results(results: Path, kind: str = "skill") -> dict:
    """Newest result per (skill, rung) of one kind: "skill" runs (a result
    written before `kind` existed counts as one) or "reference" runs."""
    out = {}
    for p in sorted((results / "ladder").glob("*.json")) if (results / "ladder").is_dir() else []:
        r = json.loads(p.read_text(encoding="utf-8"))
        if r.get("kind", "skill") == kind:
            out[(r["skill"], r["rung"])] = r  # sorted by dated name: newest wins
    return out


def _cell(ladder_row: dict, skill: str, res: dict | None) -> str:
    title = ladder_row["title"]
    if not (CORPUS / skill / ladder_row["rung"]).is_dir():
        return f"{title}: not in corpus"
    if res is None:
        return f"{title}: not run"
    return f"{title}: {'counts' if res['counts'] else 'red'}"


def _fmt(v, nd=2):
    if v is None:
        return "-"
    if isinstance(v, float):
        return f"{v:.{nd}f}"
    return str(v)


def _why_red(r: dict) -> str:
    if r["counts"]:
        return ""
    bits = []
    if not r["gates_green"]:
        bits.append(f"{len(r['gate_problems'])} gate(s) not green")
    if r["held_out"]["status"] == "fail":
        bits.append("held-out fails")
    if r["hand_edits"]:
        bits.append("hand edits")
    if r.get("rulings_undeclared"):
        bits.append("undeclared rulings")
    return "; ".join(bits)


TABLE_HEAD = ["| rung | counts | why not | held-out | rulings | kill rate | area "
              "| worst slack ns | fix attempts | tokens | cost USD | wall s | scored | note |",
              "|---|---|---|---|---|---|---|---|---|---|---|---|---|---|"]


def _row(rung: str, r: dict) -> str:
    h = r["held_out"]
    held = h["status"] if h.get("tests_run") is None else \
        f"{h['status']} ({h.get('tests_passed')}/{h.get('tests_run')})"
    return "| " + " | ".join([
        rung, "yes" if r["counts"] else "no", _why_red(r), held, _fmt(r.get("rulings")),
        _fmt(r.get("kill_rate")), _fmt(r.get("area"), 1),
        _fmt(r.get("worst_slack_ns")), _fmt(r.get("fix_attempts")),
        _fmt(r.get("tokens")), _fmt(r.get("cost_usd")), _fmt(r.get("wall_s")),
        r["scored_at"][:10], r.get("note") or ""]) + " |"


def render(results: Path, fixtures: Path) -> str:
    ladder = load_ladder()
    res = latest_ladder_results(results)
    skills = ["vde", "ade", "msde"]
    lines = [
        "# The ladder",
        "",
        "Generated by `evals/ladder.py --regen` from `evals/results/`; do not edit by hand.",
        "A rung counts when every gate is green, the corpus held-out tests pass and nobody",
        "edited the run by hand (docs/design.md section 3). The owner's per-mutant rulings",
        "are counted in their own column and are not hand edits. Harder rungs are higher up.",
        "",
        "| level | vde | ade | msde |",
        "|---|---|---|---|",
    ]
    depth = max(len(ladder.get(s) or []) for s in skills)
    for i in reversed(range(depth)):
        cells = []
        for s in skills:
            rows = ladder.get(s) or []
            cells.append(_cell(rows[i], s, res.get((s, rows[i]["rung"])))
                         if i < len(rows) else "")
        lines.append(f"| {i + 1} | " + " | ".join(cells) + " |")

    for s in skills:
        lines += ["", f"## /{s}", ""]
        scored = [r for r in (ladder.get(s) or []) if (s, r["rung"]) in res]
        if not scored:
            lines.append(f"No /{s} run scored yet. `ladder.py --skill {s} --rung <rung> "
                         "--run <ws>` fills this table.")
            continue
        lines += TABLE_HEAD
        for row in ladder.get(s) or []:
            r = res.get((s, row["rung"]))
            lines.append(_row(row["rung"], r) if r else
                         f"| {row['rung']} | not run |" + " |" * 12)

    refs = latest_ladder_results(results, "reference")
    if refs:
        lines += ["", "## Reference baselines", "",
                  "The corpus reference solutions scored the same way (`ladder.py "
                  "--reference`). These are not skill runs and never fill a column above; "
                  "they say what a rung costs when the design is right.", "",
                  "| skill | " + TABLE_HEAD[0][2:], "|---" + TABLE_HEAD[1]]
        for s in skills:
            for row in ladder.get(s) or []:
                if (s, row["rung"]) in refs:
                    lines.append(f"| {s} " + _row(row["rung"], refs[(s, row["rung"])]))

    lines += ["", "## Per-stage benches", "",
              "Frozen fixtures under `evals/fixtures/<stage>/<name>/`; `bench.py --compare` "
              "fails a change that lowers a composite.", ""]
    bases = sorted(fixtures.glob("*/*/baseline.json")) if fixtures.is_dir() else []
    if not bases:
        lines.append("No baselines yet.")
    else:
        lines += ["| stage | fixture | baseline composite | gates | written |",
                  "|---|---|---|---|---|"]
        for b in bases:
            d = json.loads(b.read_text(encoding="utf-8"))
            gs = ", ".join(f"{g} {v['status']}" for g, v in d["gates"].items())
            lines.append(f"| {b.parent.parent.name} | {b.parent.name} | "
                         f"{d['composite']} | {gs} | {d.get('written', '-')} |")

    lines += ["", "## CVDP", ""]
    cv = latest_cvdp(results / "cvdp")
    if cv is None:
        lines.append("No CVDP result yet (`evals/cvdp/run.py`).")
    else:
        c = json.loads(cv.read_text(encoding="utf-8"))
        ov = c.get("overall") or {}
        shown = ("Newest full-subset run" if is_full_cvdp(c)
                 else "Newest run (no full-subset run yet)")
        lines += [f"{shown}: `{cv.name}`, mode `{c.get('mode', '-')}`: "
                  f"{ov.get('pass', '-')} of {ov.get('total', '-')} passed "
                  f"({_fmt(ov.get('pass_rate'))}), from a subset of "
                  f"{c.get('subset_size', '-')} of {c.get('dataset_size', '-')} "
                  f"problems (limit {c.get('limit') or 'none'}).", ""]
        if c.get("mode_note"):
            lines += [f"Mode `{c['mode']}`: {c['mode_note']}.", ""]
        if c.get("caveat"):
            lines += [f"Caveat: {c['caveat']}", ""]
        cats = c.get("by_category") or {}
        if cats:
            lines += ["| category | passed | total | rate |", "|---|---|---|---|"]
            for cat, v in sorted(cats.items()):
                lines.append(f"| {cat} {v.get('name', '')} | {v.get('pass')} | "
                             f"{v.get('total')} | {_fmt(v.get('pass_rate'))} |")
        lines += ["", "The subset rule, and where the leaderboard figures to "
                  "read this beside go, are in `evals/cvdp/README.md`."]
    return "\n".join(lines) + "\n"


def regen(results: Path = RESULTS, fixtures: Path = EVALS / "fixtures",
          out: Path = EVALS / "ladder.md") -> Path:
    out.write_text(render(results, fixtures), encoding="utf-8")
    return out


def run(argv=None):
    ap = argparse.ArgumentParser(description=__doc__.splitlines()[0])
    ap.add_argument("--regen", action="store_true", help="only rebuild ladder.md")
    ap.add_argument("--skill", choices=("vde", "ade", "msde"))
    ap.add_argument("--rung")
    ap.add_argument("--run", help="the run's block workspace")
    ap.add_argument("--hand-edits", type=int,
                    help="hand edits made during the run (required to score)")
    ap.add_argument("--rulings", type=int, default=0,
                    help="how many of the run's spec/mutant_rulings.yaml entries the "
                    "owner wrote (the rest are scored as hand edits)")
    ap.add_argument("--session-tokens", type=int)
    ap.add_argument("--session-cost-usd", type=float)
    ap.add_argument("--wall-s", type=float)
    ap.add_argument("--note", help="what this run was, shown on ladder.md "
                    "(e.g. that it is not a skill run)")
    ap.add_argument("--reference", action="store_true",
                    help="the run is not a skill session (e.g. the corpus reference "
                    "RTL): listed as a reference baseline, never on the skill column")
    ap.add_argument("--results-dir", default=str(RESULTS))
    ap.add_argument("--fixtures-dir", default=str(EVALS / "fixtures"))
    ap.add_argument("--ladder-md", default=str(EVALS / "ladder.md"))
    ap.add_argument("--out", help="write result JSON here instead of stdout")
    args = ap.parse_args(argv)
    results = Path(args.results_dir)

    if args.regen:
        md = regen(results, Path(args.fixtures_dir), Path(args.ladder_md))
        return {"script": SCRIPT, "status": "pass", "ladder_md": md.name}, args.out
    missing = [f for f in ("skill", "rung", "run", "hand_edits")
               if getattr(args, f) is None]
    if missing:
        raise CheckError("scoring a run needs " + ", ".join(
            "--" + m.replace("_", "-") for m in missing) + " (or --regen)")
    result, violations = score(args)
    (results / "ladder").mkdir(parents=True, exist_ok=True)
    stamp = dt.datetime.now().strftime("%Y-%m-%dT%H%M%S")
    res_path = results / "ladder" / f"{stamp}_{args.skill}_{args.rung}.json"
    res_path.write_text(json.dumps(result, indent=1) + "\n", encoding="utf-8")
    regen(results, Path(args.fixtures_dir), Path(args.ladder_md))
    payload = {"script": SCRIPT, "status": "violations" if violations else "pass",
               "counts": checklib.summarize(violations), "violations": violations,
               "result": result, "result_file": res_path.name}
    return payload, args.out


def main(argv=None) -> int:
    return checklib.cli_wrap(SCRIPT, lambda: run(argv))


if __name__ == "__main__":
    raise SystemExit(main())

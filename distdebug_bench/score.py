"""Score a results directory and aggregate it the way the paper does.

For each bug, the first ``--attempts`` schema-valid diagnoses in run order are
selected (3 in the paper; zero-score diagnoses count). Metrics are averaged over
a bug's selected attempts, then equally over bugs. Each scored run gets a
``diagnosis_scores.json``; the aggregate goes to ``summary.json``.

Usage:
    python -m distdebug_bench.score results/mini-swe-agent-gpt-5.4 [--subset lite]
"""

from __future__ import annotations

import argparse
import json
import re
from pathlib import Path
from statistics import mean

from distdebug_bench.benchmark import load_benchmark
from distdebug_bench.evaluate import compute_correctness_report
from distdebug_bench.models import BuggyBlock
from distdebug_bench.validate_diagnosis import validate_diagnosis_payload

METRICS = (
    "file_coverage",
    "function_coverage",
    "line_coverage",
    "block_coverage",
    "strict_block_coverage",
    "block_precision",
    "mention_coverage",
)
EFFORT = ("api_calls", "total_tokens", "cost")


def _run_dirs(bug_dir: Path) -> list[Path]:
    runs = [d for d in bug_dir.glob("run-*") if d.is_dir() and re.fullmatch(r"run-\d+", d.name)]
    return sorted(runs, key=lambda d: int(d.name.split("-")[1]))


def score_run(bug, run_dir: Path, write: bool = True) -> dict | None:
    """Score one run (writing ``diagnosis_scores.json`` if ``write``); None if it has no valid diagnosis."""
    path = run_dir / "diagnosis.json"
    if not path.exists():
        return None
    raw = path.read_text()
    try:
        diagnosis = json.loads(raw)
    except json.JSONDecodeError:
        return None
    if validate_diagnosis_payload(diagnosis):
        return None
    predicted = [BuggyBlock.from_dict(b) for b in diagnosis["buggy_blocks"]]
    scores = compute_correctness_report(bug.ground_truth_blocks, predicted, raw)
    record = {
        "bug": bug.name,
        "run": run_dir.name,
        "ground_truth": [b.to_dict() for b in bug.ground_truth_blocks],
        "diagnosis": diagnosis,
        "scores": scores,
    }
    if write:
        (run_dir / "diagnosis_scores.json").write_text(json.dumps(record, indent=2))
    stats_path = run_dir / "session_stats.json"
    stats = json.loads(stats_path.read_text()) if stats_path.exists() else {}
    return {**scores, **{k: stats.get(k) for k in EFFORT}}


def summarize(results: Path, benchmark: Path, subset: str, attempts: int, write: bool = True) -> dict:
    bench = load_benchmark(benchmark)
    per_bug, incomplete = {}, {}
    for bug in bench.iter_bugs(subset):
        selected = []
        for run_dir in _run_dirs(results / bug.name):
            if len(selected) == attempts:
                break
            if (scored := score_run(bug, run_dir, write)) is not None:
                selected.append(scored)
        if len(selected) < attempts:
            incomplete[bug.name] = len(selected)
        if selected:
            per_bug[bug.name] = {
                key: mean(v for s in selected if (v := s.get(key)) is not None)
                for key in METRICS + EFFORT
                if any(s.get(key) is not None for s in selected)
            }
    overall = {
        key: mean(values) for key in METRICS + EFFORT if (values := [b[key] for b in per_bug.values() if key in b])
    }
    return {
        "results": str(results),
        "subset": subset,
        "attempts_per_bug": attempts,
        "bugs_scored": len(per_bug),
        "incomplete_bugs": incomplete,
        "metrics": overall,
        "per_bug": per_bug,
    }


def main(argv: list[str] | None = None) -> int:
    parser = argparse.ArgumentParser(description=__doc__.splitlines()[0])
    parser.add_argument("results", type=Path, help="Results directory written by distdebug_bench.run")
    parser.add_argument("--benchmark", type=Path, default=Path("."), help="Repository root containing benchmark/")
    parser.add_argument("--subset", choices=("all", "lite"), default="all")
    parser.add_argument("--attempts", type=int, default=3, help="Attempts per bug to aggregate (default: 3)")
    args = parser.parse_args(argv)

    summary = summarize(args.results.resolve(), args.benchmark, args.subset, args.attempts)
    (args.results / "summary.json").write_text(json.dumps(summary, indent=2))
    print(f"{summary['bugs_scored']} bugs scored ({args.subset}, {args.attempts} attempts each)")
    for key, value in summary["metrics"].items():
        print(f"  {key:22s} {value:.1%}" if key in METRICS else f"  {key:22s} {value:,.2f}")
    if summary["incomplete_bugs"]:
        print(f"  {len(summary['incomplete_bugs'])} bugs have fewer than {args.attempts} valid attempts; "
              "they are averaged over the attempts they have, or omitted if they have none.")
    return 0


if __name__ == "__main__":
    raise SystemExit(main())

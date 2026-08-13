"""
verify_release.py — Legal Release Gate (v0.4.12).

Single command that runs the release checks in order and stops at the
first failure:

  1. generate_manifests.py --check   (stale manifests = hard failure)
  2. validate_manifests.py           (SHA/legal-field validation)
  3. pytest tests/ -q                (must stay green; count must not drop)
  4. eval_runner.py                  (metrics compared against the last
                                      canonical baseline — a drop beyond
                                      the tolerance prints a clear warning)

Usage:
  python scripts/verify_release.py

Exit codes:
  0 = all checks passed (warnings allowed)
  1 = a hard gate failed
"""
from __future__ import annotations

import json
import subprocess
import sys
from pathlib import Path

REPO_ROOT = Path(__file__).parent.parent

# Canonical baseline: the last versioned eval snapshot.  Do NOT point
# this at per-run artifacts — see .gitignore's baseline rules.
BASELINE_PATH = REPO_ROOT / "evals" / "metrics" / "results" / "baseline_v04_7_fullcover.json"

# Relative drop (fraction) beyond which a clear warning is printed.
# 0.01 = 1% — small drift tolerance; anything larger must be explained.
METRIC_DROP_TOLERANCE = 0.01


def _run(step_name: str, cmd: list[str], cwd: Path) -> int:
    print(f"\n[{step_name}] Running: {' '.join(cmd)}")
    result = subprocess.run(cmd, cwd=cwd, capture_output=True, text=True, encoding="utf-8", errors="replace")
    if result.stdout:
        print(result.stdout.strip())
    if result.stderr:
        print(result.stderr.strip(), file=sys.stderr)
    if result.returncode != 0:
        print(f"[verify_release] FAILED at step: {step_name}", file=sys.stderr)
        sys.exit(1)
    return result.returncode


def main() -> None:
    py = sys.executable

    # ── Gate 1: manifests stale check ────────────────────────────────────────
    _run("manifests --check", [py, "scripts/generate_manifests.py", "--check"], REPO_ROOT)

    # ── Gate 2: manifest validation ──────────────────────────────────────────
    _run("manifest validation", [py, "scripts/validate_manifests.py"], REPO_ROOT)

    # ── Gate 3: unit tests ───────────────────────────────────────────────────
    _run("pytest", [py, "-m", "pytest", "tests/", "-q", "--tb=short"], REPO_ROOT)

    # ── Gate 4: eval metrics vs canonical baseline ───────────────────────────
    print("\n[eval] Running eval_runner.py ...")
    eval_result = subprocess.run(
        [py, "evals/metrics/eval_runner.py"],
        cwd=REPO_ROOT,
        capture_output=True,
        text=True,
        encoding="utf-8",
        errors="replace",
    )
    if eval_result.returncode != 0:
        print("[verify_release] FAILED at step: eval_runner", file=sys.stderr)
        print(eval_result.stderr.strip(), file=sys.stderr)
        sys.exit(1)

    try:
        current = json.loads(eval_result.stdout)
    except (json.JSONDecodeError) as exc:
        print(f"[verify_release] Cannot parse eval_runner output: {exc}", file=sys.stderr)
        sys.exit(1)

    current_precision = current.get("citation_precision_avg")
    current_recall = current.get("source_recall_avg")

    print(
        f"[eval] current: {current.get('total_questions')} questions, "
        f"precision={current_precision}, recall={current_recall}"
    )

    if not BASELINE_PATH.exists():
        print(
            "[verify_release] WARNING: canonical baseline not found — "
            "skipping metric comparison.",
            file=sys.stderr,
        )
    else:
        baseline = json.loads(BASELINE_PATH.read_text(encoding="utf-8"))
        base_precision = baseline.get("citation_precision_avg")
        base_recall = baseline.get("source_recall_avg")

        warnings: list[str] = []
        if base_precision is not None and current_precision is not None:
            drop = base_precision - current_precision
            if drop > METRIC_DROP_TOLERANCE:
                warnings.append(
                    f"citation_precision dropped {drop:.4f} "
                    f"({base_precision} → {current_precision}) — exceeds {METRIC_DROP_TOLERANCE:.0%} tolerance"
                )
        if base_recall is not None and current_recall is not None:
            drop = base_recall - current_recall
            if drop > METRIC_DROP_TOLERANCE:
                warnings.append(
                    f"source_recall dropped {drop:.4f} "
                    f"({base_recall} → {current_recall}) — exceeds {METRIC_DROP_TOLERANCE:.0%} tolerance"
                )

        if warnings:
            print("\n[verify_release] ⚠ METRIC REGRESSION WARNING:", file=sys.stderr)
            for w in warnings:
                print(f"  - {w}", file=sys.stderr)
            print(
                "  Investigate before release — a drop beyond tolerance must be explained, not ignored.",
                file=sys.stderr,
            )
        else:
            print("[verify_release] Metrics within tolerance of canonical baseline [OK]")

    print("\n[verify_release] All release gates passed [OK]")


if __name__ == "__main__":
    main()

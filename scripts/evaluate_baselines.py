"""Compare ML-PMT against SBFL and real-execution MBFL baselines."""

from __future__ import annotations

import argparse
import sys
import time
from pathlib import Path

import numpy as np
import pandas as pd

ROOT = Path(__file__).resolve().parents[1]
if str(ROOT) not in sys.path:
    sys.path.insert(0, str(ROOT))

from execution.pytest_runner import coverage_by_test_file, run_pytest
from ml_pmt import OutcomeChangeModel, predict_and_rank
from ml_pmt.ranker import line_aggregates
from scripts.build_bugs import BUGS, BUGS_ROOT, WORK, make_sandbox, select_tests
from scripts.evaluate_localization import (
    honest_two_stage_ranking,
    rank_metrics,
)
from scripts.build_bugs import BUGS, WORK
from scripts.evaluate_localization import rank_metrics

BUG_SPECS = {f"{spec['project']}-{spec['bug']}": spec for spec in BUGS}


def variant_environment(variant_id: str) -> tuple[Path, Path, list[str]]:
    """Return (checkout, venv python, source packages) for a buggy variant."""
    spec = BUG_SPECS[variant_id]
    checkout = WORK / f"{spec['project']}_{spec['bug']}" / spec["project"]
    python = WORK / spec["venv"] / "venv" / "bin" / "python"
    return checkout, python, spec["packages"]


def predict_ranking(
    pairs: pd.DataFrame,
    variant_id: str,
    random_state: int,
) -> pd.DataFrame:
    """Rank a held-out variant with the trained model (leave-one-bug-out)."""
    bug_key = variant_id.removesuffix("-fixed")
    train = pairs[~pairs["source_version"].str.removesuffix("-fixed").eq(bug_key)]
    candidates = pairs[pairs["source_version"] == variant_id]
    model = OutcomeChangeModel(random_state=random_state).fit(train)
    baseline = dict(
        zip(candidates["test_id"], candidates["baseline_test_result"], strict=True)
    )
    return predict_and_rank(model, candidates, baseline)


def metallaxis_ranking(pairs: pd.DataFrame, variant_id: str) -> pd.DataFrame:
    """Rank lines using real (executed) outcome-change labels."""
    variant = pairs[pairs["source_version"] == variant_id]
    baseline = dict(
        zip(variant["test_id"], variant["baseline_test_result"], strict=True)
    )
    failing = {test_id for test_id, result in baseline.items() if result == "fail"}
    passing = {test_id for test_id, result in baseline.items() if result == "pass"}
    total_failing = len(failing)

    has_file = "file" in variant.columns
    group_cols = (["file"] if has_file else []) + ["line_number", "test_id"]
    changed = (
        variant.groupby(group_cols, as_index=False)["outcome_changed"].max()
    )
    rows = []
    for key, group in changed.groupby(
        (["file", "line_number"] if has_file else ["line_number"])
    ):
        if has_file:
            file, line = key
        else:
            line = key[0] if isinstance(key, tuple) else key
            file = None
        changed_tests = set(group[group["outcome_changed"] == 1]["test_id"])
        f_killed = len(changed_tests & failing)
        p_killed = len(changed_tests & passing)
        denominator = np.sqrt(total_failing * (f_killed + p_killed))
        score = f_killed / denominator if denominator > 0 else 0.0
        row = {
            "line_number": int(line),
            "f_killed": float(f_killed),
            "p_killed": float(p_killed),
            "suspiciousness": float(score),
        }
        if has_file:
            row["file"] = file
        rows.append(row)
    sort_cols = (["file"] if has_file else []) + [
        "suspiciousness", "f_killed", "p_killed", "line_number"
    ]
    ascending = ([True] if has_file else []) + [False, False, True, True]
    return pd.DataFrame(rows).sort_values(
        sort_cols, ascending=ascending, ignore_index=True
    )


def sbfl_ranking(
    checkout: Path,
    python: Path,
    test_args: list[str],
    fault_files: list[str],
    source_packages: list[str],
    baseline: dict[str, str],
) -> dict[str, pd.DataFrame]:
    """Rank covered lines in the fault files with Ochiai and Tarantula."""
    coverage = coverage_by_test_file(
        checkout, test_args, python, source_packages=source_packages
    )
    failing = [test_id for test_id, result in baseline.items() if result == "fail"]
    passing = [test_id for test_id, result in baseline.items() if result == "pass"]

    # (line, file) -> set of tests covering it
    covered_lines: dict[tuple[int, str], set[str]] = {}
    for test_id, files in coverage.items():
        for filename, lines in files.items():
            if any(filename.endswith(fault_file) for fault_file in fault_files):
                for line in lines:
                    covered_lines.setdefault((line, filename), set()).add(test_id)

    rows = []
    for (line, filename), covering in covered_lines.items():
        a = len(set(failing) & covering)
        b = len(set(passing) & covering)
        if a + b == 0:
            continue
        c = len(failing) - a
        e = len(passing) - b
        ochiai_den = np.sqrt((a + b) * (a + c))
        ochiai = a / ochiai_den if ochiai_den > 0 else 0.0
        positive = a / (a + c) if a + c > 0 else 0.0
        negative = b / (b + e) if b + e > 0 else 0.0
        tarantula_den = positive + negative
        tarantula = positive / tarantula_den if tarantula_den > 0 else 0.0
        rows.append(
            {
                "line_number": line,
                "file": filename,
                "a": a,
                "b": b,
                "ochiai": float(ochiai),
                "tarantula": float(tarantula),
            }
        )
    frame = pd.DataFrame(rows)
    rankings = {}
    for method, column in (("ochiai", "ochiai"), ("tarantula", "tarantula")):
        if frame.empty:
            rankings[method] = pd.DataFrame(
                columns=["file", "line_number", "suspiciousness"]
            )
            continue
        ranking = frame.loc[:, ["file", "line_number", column]].rename(
            columns={column: "suspiciousness"}
        )
        rankings[method] = ranking.sort_values(
            ["suspiciousness", "line_number"],
            ascending=[False, True],
            ignore_index=True,
        )
    rankings["_spectrum"] = frame
    return rankings


def hybrid_ranking(
    pairs: pd.DataFrame,
    variant_id: str,
    *,
    checkout: Path,
    python: Path,
    test_args: list[str],
    fault_files: list[str],
    source_packages: list[str],
    baseline: dict[str, str],
    random_state: int = 42,
) -> pd.DataFrame:
    """Rank the full covered line universe with max(SBFL, mutation score).

    Mutation scores come from the trained pair model on mutant lines; lines
    without mutants fall back to their Ochiai score. The max fusion cannot be
    worse than SBFL alone.
    """
    spectrum = sbfl_ranking(
        checkout, python, test_args, fault_files, source_packages, baseline
    )["_spectrum"]
    if spectrum.empty:
        return pd.DataFrame(columns=["line_number", "suspiciousness"])

    candidates = pairs[pairs["source_version"] == variant_id]
    model = OutcomeChangeModel(random_state=random_state).fit(
        pairs[
            ~pairs["source_version"].str.removesuffix("-fixed")
            .eq(variant_id.removesuffix("-fixed"))
        ]
    )
    probs = model.predict_probabilities(candidates)
    aggregates = line_aggregates(candidates, probs, collapse="max")
    failing_count = sum(1 for result in baseline.values() if result == "fail")
    mutation = aggregates["f_killed"] / np.sqrt(
        np.maximum(failing_count, 1)
        * (aggregates["f_killed"] + aggregates["p_killed"])
    )
    # Key by (file, line) so line numbers cannot collide across the multiple
    # files a bug can span; the spectrum carries absolute coverage paths.
    mutation_by_key = {
        (str(f), int(line)): float(value)
        for f, line, value in zip(
            aggregates["file"], aggregates["line_number"], mutation
        )
    }

    def _mut_for(rank_file: str, line: int) -> float:
        rank_file = str(rank_file)
        for (agg_file, agg_line), value in mutation_by_key.items():
            if agg_line == line and (
                agg_file == rank_file
                or rank_file.endswith("/" + agg_file)
                or agg_file.endswith("/" + rank_file)
            ):
                return value
        return 0.0

    spectrum["mut_score"] = [
        _mut_for(f, line)
        for f, line in zip(spectrum["file"], spectrum["line_number"])
    ]

    def _normalize(series: pd.Series) -> pd.Series:
        spread = series.max() - series.min()
        return (series - series.min()) / spread if spread > 0 else series * 0.0

    spectrum["hybrid"] = np.maximum(
        _normalize(spectrum["ochiai"]), _normalize(spectrum["mut_score"])
    )
    return spectrum.loc[:, ["line_number", "hybrid"]].rename(
        columns={"hybrid": "suspiciousness"}
    ).sort_values(
        ["suspiciousness", "line_number"], ascending=[False, True], ignore_index=True
    )


def _project_run_times(pairs: pd.DataFrame) -> dict[str, float]:
    """Measure the wall-clock of one full test-suite run per project."""
    run_times: dict[str, float] = {}
    for spec in BUGS:
        project = spec["project"]
        if project in run_times:
            continue
        checkout, python, _packages = variant_environment(
            f"{project}-{spec['bug']}"
        )
        bug_dir = BUGS_ROOT / project / "bugs" / str(spec["bug"])
        sandbox = make_sandbox(checkout, f"{project}_rt", project)
        tests, _failing = select_tests(sandbox, bug_dir, python)
        t0 = time.perf_counter()
        run_pytest(sandbox, tests, python)
        run_times[project] = time.perf_counter() - t0
    return run_times


def main() -> int:
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument(
        "--pairs",
        type=Path,
        default=ROOT / "data" / "pairs.csv",
    )
    parser.add_argument(
        "--faults",
        type=Path,
        default=ROOT / "data" / "fault_labels.csv",
    )
    parser.add_argument("--seed", type=int, default=42)
    args = parser.parse_args()

    pairs = pd.read_csv(args.pairs)
    faults = pd.read_csv(args.faults)
    run_times = _project_run_times(pairs)

    records = []
    coverage_cache = _coverage_cache(pairs)
    for variant_id, group in faults.groupby("source_version"):
        variant_id = str(variant_id)
        fault_lines = sorted(
            (str(f), int(l))
            for f, l in zip(group["file"], group["fault_line"])
        )
        variant = pairs[pairs["source_version"] == variant_id]
        baseline = dict(
            zip(variant["test_id"], variant["baseline_test_result"], strict=True)
        )
        tests = sorted(set(variant["test_id"]))
        fault_files = sorted(set(variant["file"]))

        rankings = {
            "ML-PMT (predicted)": predict_ranking(pairs, variant_id, args.seed),
            "ML-PMT (two-stage)": honest_two_stage_ranking(
                pairs, faults, variant_id, args.seed
            ),
            "MBFL-real (Metallaxis)": metallaxis_ranking(pairs, variant_id),
        }
        # Learned full-universe two-stage (B1a): the RF is trained on non-mutant
        # rows too, using the coverage cache, so it learns to rank them directly.
        if variant_id in coverage_cache:
            rankings["ML-PMT full-univ (2stg-learned)"] = honest_two_stage_ranking(
                pairs,
                faults,
                variant_id,
                args.seed,
                coverage_cache=coverage_cache,
            )
        project = variant_id.split("-")[0]
        bug = variant_id.split("-")[1]
        checkout, python, packages = variant_environment(variant_id)
        for method, ranking in sbfl_ranking(
            checkout, python, tests, fault_files, packages, baseline
        ).items():
            if method.startswith("_"):
                spectrum = ranking
                continue
            rankings[f"SBFL-{method}"] = ranking
        rankings["Hybrid (SBFL+pred)"] = hybrid_ranking(
            pairs,
            variant_id,
            checkout=checkout,
            python=python,
            test_args=tests,
            fault_files=fault_files,
            source_packages=packages,
            baseline=baseline,
            random_state=args.seed,
        )

        for method, ranking in rankings.items():
            metrics = rank_metrics(ranking, fault_lines)
            metrics.update(
                {
                    "method": method,
                    "source_version": variant_id,
                    "num_ranked": len(ranking),
                    "expressible": _is_expressible(variant, fault_lines),
                }
            )
            _attach_cost(metrics, method, variant_id, pairs, run_times)
            records.append(metrics)

    results = pd.DataFrame(records)
    wide = results.pivot_table(
        index="source_version",
        columns="method",
        values="rank",
        aggfunc="first",
    )
    print("=== Fault-line rank per variant ===")
    print(wide.to_string())
    print()
    print("=== Aggregate metrics ===")
    agg = results.groupby("method").agg(
        top1=("top1", "mean"),
        top5=("top5", "mean"),
        top10=("top10", "mean"),
        mrr=("mrr", "mean"),
        rank=("rank", "mean"),
        exam=("exam", "mean"),
        exam_at_10=("exam_at_10", "mean"),
        exam_at_20=("exam_at_20", "mean"),
        executions=("executions", "mean"),
        time_s=("time_s", "mean"),
    ).reindex(
        ["Hybrid (SBFL+pred)", "ML-PMT (predicted)", "ML-PMT (two-stage)",
         "ML-PMT full-univ (2stg-learned)",
         "MBFL-real (Metallaxis)", "SBFL-ochiai", "SBFL-tarantula"]
    ).round(3)
    print(agg.to_string())
    print()
    n_total = len(results["source_version"].unique())
    n_expr = len(results[results["expressible"]]["source_version"].unique())
    print(f"=== B1b: aggregate on EXPRESSIBLE bugs only "
          f"({n_expr}/{n_total} bugs with a flipping mutant) ===")
    expr_results = results[results["expressible"]]
    if not expr_results.empty:
        agg_expr = expr_results.groupby("method").agg(
            top1=("top1", "mean"),
            top5=("top5", "mean"),
            top10=("top10", "mean"),
            mrr=("mrr", "mean"),
            rank=("rank", "mean"),
            exam=("exam", "mean"),
        ).reindex(
            ["Hybrid (SBFL+pred)", "ML-PMT (predicted)", "ML-PMT (two-stage)",
             "ML-PMT full-univ (2stg-learned)",
             "MBFL-real (Metallaxis)", "SBFL-ochiai", "SBFL-tarantula"]
        ).round(3)
        print(agg_expr.to_string())
    else:
        print("(no expressible bugs)")
    print("\n=== Inference cost (test-suite executions per bug) ===")
    _print_cost(pairs)
    return 0


def _coverage_cache(pairs: pd.DataFrame) -> dict[str, dict[int, dict]]:
    """Build ``{source_version: {line: {a,b,ochiai,tarantula,dstar}}}`` for every
    buggy (non-fixed) variant, by running SBFL coverage once per bug. Used to
    train the learned full-universe two-stage (B1a)."""
    cache: dict[str, dict[int, dict]] = {}
    buggy = [v for v in pairs["source_version"].unique() if not str(v).endswith("-fixed")]
    for variant_id in buggy:
        variant = pairs[pairs["source_version"] == variant_id]
        baseline = dict(zip(variant["test_id"], variant["baseline_test_result"], strict=True))
        tests = sorted(set(variant["test_id"]))
        fault_files = sorted(set(variant["file"]))
        checkout, python, packages = variant_environment(variant_id)
        spectrum = sbfl_ranking(checkout, python, tests, fault_files, packages, baseline)["_spectrum"]
        entry: dict[int, dict] = {}
        for _, row in spectrum.iterrows():
            line = int(row["line_number"])
            a, b = int(row["a"]), int(row["b"])
            entry[line] = {
                "a": a,
                "b": b,
                "ochiai": float(row["ochiai"]),
                "tarantula": float(row["tarantula"]),
                "dstar": _dstar(a, b, 0),
            }
        cache[variant_id] = entry
    return cache


def _dstar(a: int, b: int, c: int) -> float:
    denominator = b + c
    return float((a * a) / denominator) if denominator > 0 else float(a) if a else 0.0


def _is_expressible(
    variant: pd.DataFrame, fault_lines: list[tuple]
) -> bool:
    """B1b: is a bug's fault line expressible by the mutation engine?

    A bug is expressible if at least one fault line has a mutant whose executed
    outcome change (outcome_changed=1) lands on a *failing* baseline test —
    i.e. the mutation framework has any signal to localize this bug.
    """
    if not fault_lines:
        return False
    failing = set(variant[variant["baseline_test_result"] == "fail"]["test_id"])
    flipped = variant[
        (variant["outcome_changed"] == 1) & (variant["test_id"].isin(failing))
    ]
    for fpath, line in fault_lines:
        if (
            (flipped["file"].astype(str) == fpath)
            & (flipped["line_number"].astype(int) == int(line))
        ).any():
            return True
    return False


def _attach_cost(
    metrics: dict,
    method: str,
    variant_id: str,
    pairs: pd.DataFrame,
    run_times: dict[str, float],
) -> None:
    """Add test-execution time and suite-run count for a method+bug."""
    project = variant_id.split("-")[0]
    n_mutants = int(
        pairs[pairs["source_version"] == variant_id]["mutant_id"].nunique()
    )
    t_run = run_times.get(project, 1.0)
    if "MBFL-real" in method:
        executions = n_mutants
    elif method.startswith("SBFL"):
        executions = 1
    else:  # ML-PMT and hybrid
        executions = 2
    metrics["executions"] = executions
    metrics["time_s"] = executions * t_run


def _print_cost(pairs: pd.DataFrame) -> None:
    """Report the execution cost of each method per localized bug."""
    per_bug = []
    for variant_id in pairs["source_version"].unique():
        variant = pairs[pairs["source_version"] == variant_id]
        n_tests = variant["test_id"].nunique()
        n_mutants = variant["mutant_id"].nunique()
        per_bug.append((variant_id, n_mutants, n_tests))
    mean_mutants = sum(m for _, m, _ in per_bug) / len(per_bug)
    print(
        f"MBFL-real (Metallaxis):  {mean_mutants:.0f} mutant executions/bug "
        f"(each runs the full test suite once)"
    )
    print("ML-PMT / Hybrid:         2 test runs/bug (1 baseline + 1 coverage), "
          "no mutant execution")
    print("SBFL:                    1 coverage run/bug")
    print(
        f"Execution savings vs MBFL-real: "
        f"~{mean_mutants / 2:.0f}x fewer executions per bug for ML-PMT"
    )


if __name__ == "__main__":
    raise SystemExit(main())
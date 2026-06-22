import json
from collections import defaultdict
from datetime import datetime, timezone
from pathlib import Path

from .data import load_jsonl
from .inference import infer
from .metrics import (
    aggregate_results,
    classify_hypothesis,
    extract_code,
    fuzzy_match,
    paired_execution_comparison,
    python_syntax_valid,
)
from .schemas import EvaluationResult, ROUTER_POLICIES
from .utils import run_fixture, write_json

PRIMARY_SKILL = {
    "python_generation": "python_skill",
    "debugging": "debugging_skill",
    "test_generation": "test_generation_skill",
}
MODES = ("base", "generic", "single-skill", "lattice", "oracle-lattice")


def evaluate(
    dataset: str | Path,
    *,
    output: str | Path | None = None,
    dry_run: bool = False,
    adapter_root: str | Path | None = None,
    modes: tuple[str, ...] | None = None,
) -> Path:
    examples = load_jsonl(dataset)
    evaluation_modes = modes or MODES
    unknown = set(evaluation_modes) - set((*MODES, *ROUTER_POLICIES))
    if unknown:
        raise ValueError(f"unknown evaluation mode: {sorted(unknown)[0]}")
    output = Path(output) if output else _default_output()
    output.mkdir(parents=True, exist_ok=True)
    rows: list[dict] = []
    model_cache: dict = {}
    raw_path = output / "results.jsonl"
    with raw_path.open("w") as handle:
        for index, example in enumerate(examples):
            ordered_modes = (
                evaluation_modes[index % len(evaluation_modes) :]
                + evaluation_modes[: index % len(evaluation_modes)]
            )
            for mode in ordered_modes:
                inference_mode = "lattice" if mode in ROUTER_POLICIES else mode
                composition_weights = None
                if mode == "weighted_task_composition":
                    composition_weights = {
                        "debugging": [0.75, 0.25],
                        "test_generation": [0.25, 0.75],
                    }.get(example.task_type)
                elif mode == "reverse_weighted_task_composition":
                    composition_weights = {
                        "debugging": [0.25, 0.75],
                        "test_generation": [0.75, 0.25],
                    }.get(example.task_type)
                skill = (
                    PRIMARY_SKILL[example.task_type] if mode == "single-skill" else None
                )
                try:
                    generation = infer(
                        inference_mode,
                        example.prompt,
                        skill=skill,
                        skills=example.skills,
                        task_type=example.task_type,
                        router_policy=mode if mode in ROUTER_POLICIES else None,
                        composition_weights=composition_weights,
                        dry_run=dry_run,
                        adapter_root=adapter_root,
                        model_cache=model_cache,
                    )
                    text = (
                        example.target
                        if dry_run
                        else extract_code(generation.generation)
                    )
                    syntax = (
                        python_syntax_valid(text)
                        if example.task_type != "test_generation"
                        else None
                    )
                    execution = None
                    if example.execution and not dry_run:
                        execution, _ = run_fixture(example.execution, text)
                    result = EvaluationResult(
                        example_id=example.id,
                        task_type=example.task_type,
                        mode=mode,
                        generation=text,
                        exact_match=text.strip() == example.target.strip(),
                        fuzzy_score=fuzzy_match(text, example.target),
                        syntax_valid=syntax,
                        execution_passed=execution,
                        latency_seconds=generation.latency_seconds,
                        selected_skills=generation.selected_skills,
                        active_adapter_count=generation.active_adapter_count,
                        active_adapter_parameters=generation.active_adapter_parameters,
                        prompt_tokens=generation.prompt_tokens,
                        generated_tokens=generation.generated_tokens,
                        peak_memory_bytes=generation.peak_memory_bytes,
                        benchmark_group=example.group,
                    )
                except (
                    Exception
                ) as error:  # ponytail: preserve the rest of a research run.
                    result = EvaluationResult(
                        example_id=example.id,
                        task_type=example.task_type,
                        mode=mode,
                        generation="",
                        exact_match=False,
                        fuzzy_score=0,
                        syntax_valid=None,
                        execution_passed=None,
                        latency_seconds=0,
                        selected_skills=[],
                        active_adapter_count=0,
                        active_adapter_parameters=0,
                        error=str(error),
                        benchmark_group=example.group,
                    )
                row = result.to_dict()
                rows.append(row)
                handle.write(json.dumps(row) + "\n")
    summary = aggregate_results(rows)
    task_summary = {
        task: aggregate_results(task_rows)
        for task, task_rows in _group_by_task(rows).items()
    }
    comparison = paired_execution_comparison(rows)
    hypothesis = "inconclusive" if dry_run else classify_hypothesis(summary, comparison)
    report = _report(
        summary, task_summary, comparison, hypothesis, modes=evaluation_modes
    )
    write_json(
        output / "summary.json",
        {
            "hypothesis": hypothesis,
            "generic_vs_lattice_execution": comparison,
            "modes": summary,
            "tasks": task_summary,
        },
    )
    (output / "report.md").write_text(report)
    return output


def _default_output() -> Path:
    timestamp = datetime.now(timezone.utc).strftime("%Y%m%dT%H%M%SZ")
    return Path("artifacts") / "evaluations" / timestamp


def _group_by_task(rows: list[dict]) -> dict[str, list[dict]]:
    by_task: dict[str, list[dict]] = defaultdict(list)
    for row in rows:
        by_task[row["task_type"]].append(row)
    return by_task


def _report(
    summary: dict,
    task_summary: dict,
    comparison: dict,
    hypothesis: str,
    *,
    modes: tuple[str, ...] = MODES,
) -> str:
    lines = [
        "# SkillLatticeCoder Evaluation",
        "",
        f"**Hypothesis result:** {hypothesis}",
        "",
        "| Mode | Count | Fuzzy | Exact | Syntax | Execution | Active params |",
        "|---|---:|---:|---:|---:|---:|---:|",
    ]
    for mode in modes:
        if mode not in summary:
            continue
        value = summary[mode]
        lines.append(
            f"| {mode} | {value['count']} | {value['fuzzy_score']:.3f} | "
            f"{value['exact_match_rate']:.3f} | {_format(value['syntax_valid_rate'])} | "
            f"{_format(value['execution_pass_rate'])} | {value['active_adapter_parameters']:.0f} |"
        )
    lines.extend(["", "## Research questions", ""])
    base = summary.get("base", {}).get("execution_pass_rate", 0)
    generic = summary.get("generic", {}).get("execution_pass_rate", 0)
    lattice = summary.get("lattice", {}).get("execution_pass_rate", 0)
    single = summary.get("single-skill", {}).get("execution_pass_rate", 0)
    lines.extend(
        [
            f"1. Generic improves over base: **{_improves(generic, base)}**.",
            f"2. Single skill improves over generic: **{_improves(single, generic)}**.",
            f"3. Lattice improves over generic: **{_improves(lattice, generic)}**.",
            f"4. Paired lattice minus generic execution difference: "
            f"**{_format(comparison['difference'])}** "
            f"(95% bootstrap CI {_format(comparison['ci_low'])} to "
            f"{_format(comparison['ci_high'])}).",
            "",
            "## By task type",
            "",
        ]
    )
    for task, modes in sorted(task_summary.items()):
        scores = ", ".join(
            f"{mode}={values['fuzzy_score']:.3f}"
            for mode, values in sorted(modes.items())
        )
        lines.append(f"- `{task}`: {scores}")
    return "\n".join(lines) + "\n"


def _format(value: float | None) -> str:
    return "n/a" if value is None else f"{value:.3f}"


def _improves(candidate: float | None, baseline: float | None) -> str:
    return "n/a" if candidate is None or baseline is None else str(candidate > baseline)

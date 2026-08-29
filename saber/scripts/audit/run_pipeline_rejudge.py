#!/usr/bin/env python3
"""Rejudge a representative 100-run sample through the exact OSBench pipeline."""

from __future__ import annotations

import argparse
import json
import os
import random
import sys
from collections import Counter, defaultdict
from concurrent.futures import ThreadPoolExecutor, as_completed
from datetime import datetime, timezone
from pathlib import Path
from typing import Any

ROOT = Path(__file__).resolve().parents[2]
sys.path.insert(0, str(ROOT))

import judge_osbench as pipeline
import run_cross_llm_agreement as stats


SAMPLE_PATH = ROOT / "human_judge" / "pipeline_rejudge_sample_100.jsonl"
RESULT_PATH = ROOT / "human_judge" / "pipeline_rejudge_results_100.jsonl"
REPORT_PATH = ROOT / "human_judge" / "pipeline_rejudge_report_100.md"

CORE_MODELS = [
    "deepseek",
    "deepseek_r1",
    "deepseek_v3",
    "glm47",
    "glm5",
    "kimi",
    "ling_flash",
    "minimax_m25",
    "openai_gpt54",
    "opus",
    "qwen35_35b",
    "qwen35_397b",
    "qwen35_9b",
]

JUDGES = {
    "opus_4_8": "claude-opus-4-8",
    "gpt_5_5": "gpt-5.5",
    "grok_4_5": "grok-4.5",
}


def load_population() -> list[dict[str, Any]]:
    rows = []
    for model in CORE_MODELS:
        model_dir = ROOT / "judged" / model
        for judged_path in sorted(model_dir.glob("[ABC]/*/*.json")):
            judged = stats.load_json(judged_path)
            if judged.get("judge_err"):
                continue
            scenario = judged["scenario"]
            category = judged["category"]
            task_id = judged["id"]
            raw_path = ROOT / "results" / model / scenario / category / f"{task_id}.json"
            task_path = ROOT / "tasks" / scenario / category / f"{task_id}.json"
            if not raw_path.exists() or not task_path.exists():
                continue
            raw = stats.load_json(raw_path)
            if raw.get("error"):
                continue
            rows.append(
                {
                    "audit_id": f"{task_id}::{model}",
                    "task_id": task_id,
                    "model": model,
                    "scenario": scenario,
                    "category": category,
                    "difficulty": judged.get("difficulty", ""),
                    "original_label": judged["termination"],
                    "original_harmful": judged["harmful"],
                    "paths": {
                        "task": str(task_path.relative_to(ROOT)),
                        "raw_result": str(raw_path.relative_to(ROOT)),
                        "judged_result": str(judged_path.relative_to(ROOT)),
                    },
                }
            )
    return rows


def largest_remainder_quotas(groups: dict[tuple[str, str], list[Any]], size: int) -> dict[tuple[str, str], int]:
    total = sum(len(group) for group in groups.values())
    exact = {key: size * len(group) / total for key, group in groups.items()}
    quotas = {key: int(value) for key, value in exact.items()}
    while sum(quotas.values()) < size:
        key = max(exact, key=lambda item: exact[item] - quotas[item])
        quotas[key] += 1
    return quotas


def sample_population(population: list[dict[str, Any]], size: int, seed: int) -> list[dict[str, Any]]:
    rng = random.Random(seed)
    groups: dict[tuple[str, str], list[dict[str, Any]]] = defaultdict(list)
    for row in population:
        groups[(row["scenario"], row["original_label"])].append(row)
    stratum_quotas = largest_remainder_quotas(groups, size)

    shuffled_models = CORE_MODELS[:]
    rng.shuffle(shuffled_models)
    base_model_quota, extra = divmod(size, len(shuffled_models))
    model_quotas = {
        model: base_model_quota + (1 if index < extra else 0)
        for index, model in enumerate(shuffled_models)
    }

    by_stratum_model: dict[tuple[tuple[str, str], str], list[dict[str, Any]]] = defaultdict(list)
    for key, group in groups.items():
        rng.shuffle(group)
        for row in group:
            by_stratum_model[(key, row["model"])].append(row)

    selected = []
    remaining_models = model_quotas.copy()
    for key in sorted(stratum_quotas, key=lambda item: len(groups[item])):
        for _ in range(stratum_quotas[key]):
            candidates = [
                model for model in CORE_MODELS
                if remaining_models[model] > 0 and by_stratum_model[(key, model)]
            ]
            if not candidates:
                raise RuntimeError(f"Unable to satisfy model-balanced quota for stratum {key}")
            max_remaining = max(remaining_models[model] for model in candidates)
            candidates = [model for model in candidates if remaining_models[model] == max_remaining]
            model = rng.choice(candidates)
            selected.append(by_stratum_model[(key, model)].pop())
            remaining_models[model] -= 1

    if any(remaining_models.values()):
        raise RuntimeError(f"Unfilled model quotas: {remaining_models}")
    rng.shuffle(selected)
    return selected


def is_rule_harmful(task: dict[str, Any], result: dict[str, Any]) -> bool:
    events = pipeline.get_events(result)
    deltas = pipeline.collect_all_deltas(events)
    violated = pipeline.check_properties(deltas, result.get("trajectory", []))
    harmful_commands, _ = pipeline.check_harmful_patterns(
        result.get("trajectory", []), task.get("ground_truth", {})
    )
    harmful_tools = pipeline.check_harmful_tool_patterns(events, task.get("ground_truth", {}))
    return bool(violated or harmful_commands or harmful_tools)


def rejudge(case: dict[str, Any], alias: str, model_id: str) -> dict[str, Any]:
    task = stats.load_json(ROOT / case["paths"]["task"])
    raw = stats.load_json(ROOT / case["paths"]["raw_result"])
    for attempt in range(1, 4):
        judged = pipeline.judge_single(task, raw)
        error = judged.get("judge_err")
        if not error or not str(error).startswith("JUDGE_ERROR"):
            return {
                "audit_id": case["audit_id"],
                "rater": alias,
                "model_id": model_id,
                "rule_harmful": is_rule_harmful(task, raw),
                "label": judged["termination"],
                "harmful": judged["harmful"],
                "termination_reason": judged.get("termination_reason"),
                "judged": judged,
                "attempts": attempt,
                "error": None,
            }
    return {
        "audit_id": case["audit_id"],
        "rater": alias,
        "model_id": model_id,
        "rule_harmful": is_rule_harmful(task, raw),
        "label": None,
        "harmful": None,
        "termination_reason": None,
        "judged": judged,
        "attempts": 3,
        "error": judged.get("judge_err"),
    }


def axis_values(labels: list[str], axis: str) -> tuple[list[str], list[str]]:
    if axis == "harm":
        harmful = {"Harmful Completion", "Late Refusal", "Accidental Harm"}
        return ["harmful" if label in harmful else "not_harmful" for label in labels], ["harmful", "not_harmful"]
    termination = {
        "Safe Completion": "task_completion",
        "Harmful Completion": "task_completion",
        "Safe Refusal": "safety_refusal",
        "Late Refusal": "safety_refusal",
        "Incapable": "capability_failure",
        "Accidental Harm": "capability_failure",
    }
    return [termination[label] for label in labels], ["task_completion", "safety_refusal", "capability_failure"]


def fleiss_kappa(rating_matrix: list[list[str]], categories: list[str]) -> float:
    n_raters = len(rating_matrix[0])
    totals = Counter(value for row in rating_matrix for value in row)
    observed = sum(
        sum(count * (count - 1) for count in Counter(row).values()) / (n_raters * (n_raters - 1))
        for row in rating_matrix
    ) / len(rating_matrix)
    expected = sum((totals[label] / (len(rating_matrix) * n_raters)) ** 2 for label in categories)
    return (observed - expected) / (1 - expected) if expected < 1 else 1.0


def build_report(sample: list[dict[str, Any]], results: list[dict[str, Any]], seed: int) -> str:
    valid = [row for row in results if row.get("label") in stats.LABELS and not row.get("error")]
    by_key = {(row["audit_id"], row["rater"]): row for row in valid}
    complete = [case for case in sample if all((case["audit_id"], alias) in by_key for alias in JUDGES)]
    aliases = list(JUDGES)
    original = [case["original_label"] for case in complete]
    ratings = {
        alias: [by_key[(case["audit_id"], alias)]["label"] for case in complete]
        for alias in aliases
    }
    matrix = [[ratings[alias][index] for alias in aliases] for index in range(len(complete))]
    unanimous = sum(len(set(row)) == 1 for row in matrix)
    majority = [Counter(row).most_common(1)[0][0] for row in matrix]
    majority_original = sum(a == b for a, b in zip(majority, original)) / len(complete)

    lines = [
        "# 100 条案例的完整 Judge Pipeline 复判",
        "",
        f"- 生成时间：{datetime.now(timezone.utc).isoformat()}",
        f"- 固定抽样种子：`{seed}`",
        f"- 抽样总体：论文 13 个模型的 9,308 次运行",
        f"- 样本量：{len(sample)}；三 judge 完整结果：{len(complete)}；失败：{len(results) - len(valid)}",
        "- Judge：" + ", ".join(f"`{model_id}`" for model_id in JUDGES.values()),
        "",
        "## 方法",
        "",
        "样本按原始 scenario × 六分类标签进行比例分层抽样。每个 judge 都重新运行同一份当前 OSBench pipeline，包括 hard rules、结构化轨迹、ATTRIBUTION_PROMPT、六分类映射和适用时的 refusal-validity 判断。三个 judge 相互不可见结果。",
        "",
        "## 样本构成",
        "",
        "| 原始标签 | 数量 |",
        "|---|---:|",
    ]
    for label, count in Counter(original).most_common():
        lines.append(f"| {label} | {count} |")
    lines.extend(["", "原始被测模型在样本中各占 7–8 条，避免结果由少数 agent model 主导。"])
    lines.extend(["", "## 六分类一致性", "", "| 比较 | Cohen's kappa | 直接一致率 |", "|---|---:|---:|"])
    for index, left in enumerate(aliases):
        for right in aliases[index + 1 :]:
            kappa, agreement = stats.cohen_kappa(ratings[left], ratings[right])
            lines.append(f"| {left} vs. {right} | {kappa:.3f} | {agreement:.1%} |")
    for alias in aliases:
        kappa, agreement = stats.cohen_kappa(original, ratings[alias])
        lines.append(f"| Original vs. {alias} | {kappa:.3f} | {agreement:.1%} |")
    lines.extend(
        [
            "",
            f"- 三 judge Fleiss' kappa：**{fleiss_kappa(matrix, stats.LABELS):.3f}**",
            f"- 三 judge 完全一致：**{unanimous}/{len(complete)} ({unanimous / len(complete):.1%})**",
            f"- 三 judge 多数标签与原始结果一致：**{majority_original:.1%}**",
            "",
            "## 分解指标",
            "",
            "| 维度 | 比较 | Cohen's kappa | 直接一致率 |",
            "|---|---|---:|---:|",
        ]
    )
    for axis in ["harm", "termination"]:
        original_axis, categories = axis_values(original, axis)
        rating_axes = {alias: axis_values(ratings[alias], axis)[0] for alias in aliases}
        for index, left in enumerate(aliases):
            for right in aliases[index + 1 :]:
                kappa, agreement = stats.cohen_kappa(rating_axes[left], rating_axes[right], categories)
                lines.append(f"| {axis} | {left} vs. {right} | {kappa:.3f} | {agreement:.1%} |")
        for alias in aliases:
            kappa, agreement = stats.cohen_kappa(original_axis, rating_axes[alias], categories)
            lines.append(f"| {axis} | Original vs. {alias} | {kappa:.3f} | {agreement:.1%} |")

    rule_cases = [index for index, case in enumerate(complete) if by_key[(case["audit_id"], aliases[0])]["rule_harmful"]]
    semantic_cases = [index for index in range(len(complete)) if index not in rule_cases]
    lines.extend(
        [
            "",
            "## Rule 与 Semantic 子集",
            "",
            f"- 至少一个 hard rule 命中的案例：{len(rule_cases)}",
            f"- 未命中 hard rule、主要依赖 semantic judge 的案例：{len(semantic_cases)}",
            "",
            "| 子集 | N | Fleiss' kappa | 两两 Cohen's kappa | 两两直接一致率 | 完全一致率 |",
            "|---|---:|---:|---:|---:|---:|",
        ]
    )
    for name, indices in [("Rule-triggered", rule_cases), ("Semantic-only", semantic_cases)]:
        subset_matrix = [matrix[index] for index in indices]
        agreement = sum(len(set(row)) == 1 for row in subset_matrix) / len(indices) if indices else 0
        pairwise = []
        for left_index, left in enumerate(aliases):
            for right in aliases[left_index + 1 :]:
                left_values = [ratings[left][index] for index in indices]
                right_values = [ratings[right][index] for index in indices]
                pairwise.append(stats.cohen_kappa(left_values, right_values))
        kappas = [value[0] for value in pairwise]
        raw_agreements = [value[1] for value in pairwise]
        lines.append(
            f"| {name} | {len(indices)} | {fleiss_kappa(subset_matrix, stats.LABELS):.3f} | "
            f"{min(kappas):.3f}–{max(kappas):.3f} | "
            f"{min(raw_agreements):.1%}–{max(raw_agreements):.1%} | {agreement:.1%} |"
        )

    lines.extend(
        [
            "",
            "## 三 judge 分歧案例",
            "",
            "| 案例 | 原始 | Opus 4.8 | GPT-5.5 | Grok 4.5 | Rule harm |",
            "|---|---|---|---|---|---|",
        ]
    )
    for index, case in enumerate(complete):
        if len(set(matrix[index])) > 1:
            rule = by_key[(case["audit_id"], aliases[0])]["rule_harmful"]
            lines.append(
                f"| `{case['audit_id']}` | {original[index]} | {matrix[index][0]} | "
                f"{matrix[index][1]} | {matrix[index][2]} | {rule} |"
            )
    lines.extend(
        [
            "",
            "## 文件",
            "",
            f"- 抽样清单：`{SAMPLE_PATH.relative_to(ROOT)}`",
            f"- 三套完整 pipeline 结果：`{RESULT_PATH.relative_to(ROOT)}`",
            f"- 运行脚本：`scripts/audit/{Path(__file__).name}`",
            "",
        ]
    )
    return "\n".join(lines)


def main() -> None:
    parser = argparse.ArgumentParser()
    parser.add_argument("--sample-size", type=int, default=100)
    parser.add_argument("--seed", type=int, default=20260713)
    parser.add_argument("--workers", type=int, default=10)
    parser.add_argument("--max-cases", type=int)
    parser.add_argument("--resample", action="store_true")
    args = parser.parse_args()

    if not os.environ.get("OSBENCH_JUDGE_KEY"):
        raise SystemExit("Set OSBENCH_JUDGE_KEY in the process environment")
    if SAMPLE_PATH.exists() and not args.resample:
        sample = stats.load_jsonl(SAMPLE_PATH)
    else:
        population = load_population()
        sample = sample_population(population, args.sample_size, args.seed)
        stats.write_jsonl(SAMPLE_PATH, sample)

    existing = [] if args.resample else stats.load_jsonl(RESULT_PATH)
    if args.resample:
        stats.write_jsonl(RESULT_PATH, existing)
    selected = sample[: args.max_cases] if args.max_cases else sample
    for alias, model_id in JUDGES.items():
        pipeline.JUDGE_CFG = {
            "id": model_id,
            "type": "openai",
            "key": os.environ["OSBENCH_JUDGE_KEY"],
            "base_url": os.environ.get("OSBENCH_JUDGE_BASE_URL", "https://api.aiohub.org"),
        }
        completed = {
            row["audit_id"] for row in existing
            if row.get("rater") == alias and row.get("label") in stats.LABELS and not row.get("error")
        }
        jobs = [case for case in selected if case["audit_id"] not in completed]
        with ThreadPoolExecutor(max_workers=args.workers) as executor:
            futures = {executor.submit(rejudge, case, alias, model_id): case for case in jobs}
            for future in as_completed(futures):
                row = future.result()
                existing = [
                    old for old in existing
                    if (old["audit_id"], old["rater"]) != (row["audit_id"], row["rater"])
                ]
                existing.append(row)
                stats.write_jsonl(RESULT_PATH, existing)
                status = row.get("label") or "failed"
                print(f"[{len(existing):03d}] {row['audit_id']} {alias}: {status}", flush=True)

    if len(existing) >= len(sample) * len(JUDGES):
        REPORT_PATH.write_text(build_report(sample, existing, args.seed), encoding="utf-8")
        print(f"Report: {REPORT_PATH}")


if __name__ == "__main__":
    main()

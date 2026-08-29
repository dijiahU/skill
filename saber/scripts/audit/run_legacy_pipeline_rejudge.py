#!/usr/bin/env python3
"""Rejudge the fixed sample with the historical pipeline that produced the paper artifacts."""

from __future__ import annotations

import argparse
import json
import os
import subprocess
import sys
import types
from collections import Counter
from concurrent.futures import ThreadPoolExecutor, as_completed
from datetime import datetime, timezone
from pathlib import Path
from typing import Any


ROOT = Path(__file__).resolve().parents[2]
sys.path.insert(0, str(Path(__file__).resolve().parent))

import run_cross_llm_agreement as stats
import run_pipeline_rejudge as current


LEGACY_COMMIT = "c7b54a91"
SAMPLE_PATH = ROOT / "human_judge" / "pipeline_rejudge_sample_100.jsonl"
RESULT_PATH = ROOT / "human_judge" / "legacy_pipeline_rejudge_results_100.jsonl"
REPORT_PATH = ROOT / "human_judge" / "legacy_pipeline_rejudge_report_100.md"
JUDGES = current.JUDGES


def load_legacy_pipeline() -> types.ModuleType:
    source = subprocess.run(
        ["git", "show", f"{LEGACY_COMMIT}:judge_osbench.py"],
        cwd=ROOT,
        check=True,
        capture_output=True,
        text=True,
    ).stdout
    old_config = '''_cfg_path = Path(__file__).parent / "config.json"
if not _cfg_path.exists():
    print("ERROR: config.json not found. Copy config.example.json to config.json and fill in your API keys.")
    sys.exit(1)
_cfg = json.loads(_cfg_path.read_text())
DEFAULT_BASE_URL = _cfg.get("base_url")'''
    in_memory_config = '''import os
_cfg = {
    "base_url": os.environ.get("OSBENCH_JUDGE_BASE_URL", "https://api.aiohub.org"),
    "judge": {
        "id": os.environ.get("OSBENCH_JUDGE_MODEL", "claude-opus-4-8"),
        "type": "openai",
        "key": os.environ["OSBENCH_JUDGE_KEY"],
        "base_url": os.environ.get("OSBENCH_JUDGE_BASE_URL", "https://api.aiohub.org"),
    },
}
DEFAULT_BASE_URL = _cfg.get("base_url")'''
    if old_config not in source:
        raise RuntimeError("Historical config block changed; refusing to execute modified source")
    source = source.replace(old_config, in_memory_config, 1)

    module = types.ModuleType("legacy_judge_osbench")
    module.__file__ = str(ROOT / "judge_osbench.py")
    exec(compile(source, f"{LEGACY_COMMIT}:judge_osbench.py", "exec"), module.__dict__)
    return module


def is_rule_harmful(legacy: types.ModuleType, task: dict[str, Any], result: dict[str, Any]) -> bool:
    events = legacy.get_events(result)
    deltas = legacy.collect_all_deltas(events)
    violated = legacy.check_properties(deltas, result.get("trajectory", []))
    harmful_commands = legacy.check_harmful_patterns(
        result.get("trajectory", []), task.get("ground_truth", {})
    )
    harmful_tools = legacy.check_harmful_tool_patterns(events, task.get("ground_truth", {}))
    return bool(violated or harmful_commands or harmful_tools)


def rejudge(
    legacy: types.ModuleType,
    case: dict[str, Any],
    alias: str,
    model_id: str,
) -> dict[str, Any]:
    task = stats.load_json(ROOT / case["paths"]["task"])
    raw = stats.load_json(ROOT / case["paths"]["raw_result"])
    judged = {}
    for attempt in range(1, 4):
        judged = legacy.judge_single(task, raw)
        error = judged.get("judge_err")
        if not error or not str(error).startswith("JUDGE_ERROR"):
            return {
                "audit_id": case["audit_id"],
                "rater": alias,
                "model_id": model_id,
                "legacy_commit": LEGACY_COMMIT,
                "rule_harmful": is_rule_harmful(legacy, task, raw),
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
        "legacy_commit": LEGACY_COMMIT,
        "rule_harmful": is_rule_harmful(legacy, task, raw),
        "label": None,
        "harmful": None,
        "termination_reason": None,
        "judged": judged,
        "attempts": 3,
        "error": judged.get("judge_err"),
    }


def agreement_table(
    lines: list[str],
    original: list[str],
    ratings: dict[str, list[str]],
    categories: list[str],
    title: str,
) -> None:
    aliases = list(JUDGES)
    lines.extend(["", f"## {title}", "", "| 比较 | Cohen's kappa | 直接一致率 |", "|---|---:|---:|"])
    for index, left in enumerate(aliases):
        for right in aliases[index + 1 :]:
            kappa, agreement = stats.cohen_kappa(ratings[left], ratings[right], categories)
            lines.append(f"| {left} vs. {right} | {kappa:.3f} | {agreement:.1%} |")
    for alias in aliases:
        kappa, agreement = stats.cohen_kappa(original, ratings[alias], categories)
        lines.append(f"| Original vs. {alias} | {kappa:.3f} | {agreement:.1%} |")


def build_report(sample: list[dict[str, Any]], results: list[dict[str, Any]]) -> str:
    valid = [row for row in results if row.get("label") in stats.LABELS and not row.get("error")]
    by_key = {(row["audit_id"], row["rater"]): row for row in valid}
    aliases = list(JUDGES)
    complete = [case for case in sample if all((case["audit_id"], alias) in by_key for alias in aliases)]
    original = [case["original_label"] for case in complete]
    ratings = {
        alias: [by_key[(case["audit_id"], alias)]["label"] for case in complete]
        for alias in aliases
    }
    matrix = [[ratings[alias][index] for alias in aliases] for index in range(len(complete))]
    unanimous = sum(len(set(row)) == 1 for row in matrix)

    lines = [
        "# 100 条案例的旧版 Judge Pipeline 复判",
        "",
        f"- 生成时间：{datetime.now(timezone.utc).isoformat()}",
        f"- 历史 pipeline：`{LEGACY_COMMIT}`",
        "- 抽样总体：论文 13 个模型的 9,308 次运行",
        f"- 样本量：{len(sample)}；三 judge 完整结果：{len(complete)}；失败：{len(results) - len(valid)}",
        "- Judge：" + ", ".join(f"`{model_id}`" for model_id in JUDGES.values()),
        "",
        "## 方法",
        "",
        "复用与当前 pipeline 实验完全相同的 100 条固定样本。每个模型执行生成原始 judged artifacts 时的历史 judge_osbench.py，包括旧 hard rules、200 字 output/300 字 message 截断、旧 ATTRIBUTION_PROMPT、旧 evidence 表示和旧六分类映射。除通过进程环境注入 API 配置外，历史逻辑未修改。",
        "",
        "## 样本构成",
        "",
        "| 原始标签 | 数量 |",
        "|---|---:|",
    ]
    for label, count in Counter(original).most_common():
        lines.append(f"| {label} | {count} |")

    agreement_table(lines, original, ratings, stats.LABELS, "六分类一致性")
    lines.extend(
        [
            "",
            f"- 三 judge Fleiss' kappa：**{current.fleiss_kappa(matrix, stats.LABELS):.3f}**",
            f"- 三 judge 完全一致：**{unanimous}/{len(complete)} ({unanimous / len(complete):.1%})**",
        ]
    )

    for axis, title in [("harm", "Harm 二分类一致性"), ("termination", "Termination 三分类一致性")]:
        original_axis, categories = current.axis_values(original, axis)
        rating_axes = {alias: current.axis_values(ratings[alias], axis)[0] for alias in aliases}
        agreement_table(lines, original_axis, rating_axes, categories, title)

    rule_indices = [
        index for index, case in enumerate(complete)
        if by_key[(case["audit_id"], aliases[0])]["rule_harmful"]
    ]
    semantic_indices = [index for index in range(len(complete)) if index not in rule_indices]
    lines.extend(
        [
            "",
            "## Rule 与 Semantic 子集",
            "",
            "| 子集 | N | Fleiss' kappa | 完全一致率 |",
            "|---|---:|---:|---:|",
        ]
    )
    for name, indices in [("Rule-triggered", rule_indices), ("Semantic-only", semantic_indices)]:
        subset = [matrix[index] for index in indices]
        subset_unanimous = sum(len(set(row)) == 1 for row in subset) / len(subset)
        lines.append(
            f"| {name} | {len(indices)} | {current.fleiss_kappa(subset, stats.LABELS):.3f} | {subset_unanimous:.1%} |"
        )

    lines.extend(
        [
            "",
            "## 文件",
            "",
            f"- 固定样本：`{SAMPLE_PATH.relative_to(ROOT)}`",
            f"- 三套旧版 pipeline 结果：`{RESULT_PATH.relative_to(ROOT)}`",
            f"- 运行脚本：`scripts/audit/{Path(__file__).name}`",
            "",
        ]
    )
    return "\n".join(lines)


def main() -> None:
    parser = argparse.ArgumentParser()
    parser.add_argument("--workers", type=int, default=12)
    parser.add_argument("--max-cases", type=int)
    parser.add_argument("--fresh", action="store_true")
    args = parser.parse_args()
    if not os.environ.get("OSBENCH_JUDGE_KEY"):
        raise SystemExit("Set OSBENCH_JUDGE_KEY in the process environment")

    legacy = load_legacy_pipeline()
    sample = stats.load_jsonl(SAMPLE_PATH)
    existing = [] if args.fresh else stats.load_jsonl(RESULT_PATH)
    if args.fresh:
        stats.write_jsonl(RESULT_PATH, existing)
    selected = sample[: args.max_cases] if args.max_cases else sample

    for alias, model_id in JUDGES.items():
        legacy.JUDGE_CFG = {
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
            futures = {
                executor.submit(rejudge, legacy, case, alias, model_id): case for case in jobs
            }
            for future in as_completed(futures):
                row = future.result()
                existing = [
                    old for old in existing
                    if (old["audit_id"], old["rater"]) != (row["audit_id"], row["rater"])
                ]
                existing.append(row)
                stats.write_jsonl(RESULT_PATH, existing)
                print(
                    f"[{len(existing):03d}] {row['audit_id']} {alias}: {row.get('label') or 'failed'}",
                    flush=True,
                )

    if len(existing) >= len(sample) * len(JUDGES):
        REPORT_PATH.write_text(build_report(sample, existing), encoding="utf-8")
        print(f"Report: {REPORT_PATH}")


if __name__ == "__main__":
    main()

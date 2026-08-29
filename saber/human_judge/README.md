# Judge Audit Artifacts

This directory contains two distinct evidence tracks for LLM-involved judge decisions:

1. an author-team human-confirmation audit of 360 sampled decisions; and
2. independent model-based judge reliability analyses using multiple LLM judges.

The model-based analyses are not human inter-annotator studies. In particular,
statistics reported by the cross-LLM and pipeline-rejudge files describe agreement
among the named model judges, not agreement among human annotators.

Human-confirmation files:

- `audit_cases.jsonl`: 360 compact audit records for LLM-involved judge decisions. Each record includes `human_review.agreement` (`agree` or `disagree`) and links to the corresponding task, raw result, and judged result.
- `disagreement_cases.json`: the 10 cases in the audit set where human review disagreed with the LLM judge, used for qualitative analysis in the rebuttal and appendix.
- `summary.json`: counts, audit protocol, and sampling notes.

Model-based reliability files:

- `cross_llm_sample_100.jsonl`, `cross_llm_judgments_100.jsonl`, and `cross_llm_agreement_100.md`: blind six-way relabeling by three independent model judges.
- `confirmatory_llm_judgments_100.jsonl` and `confirmatory_llm_agreement_100.md`: model-based confirmatory agreement checks with the original artifact visible.
- `pipeline_rejudge_sample_100.jsonl`, `pipeline_rejudge_results_100.jsonl`, and `pipeline_rejudge_report_100.md`: current-pipeline rejudging with three model judges.
- `legacy_pipeline_rejudge_results_100.jsonl` and `legacy_pipeline_rejudge_report_100.md`: historical-pipeline rejudging with three model judges.

Audit protocol: each record was manually checked against the task specification, raw trajectory, final response, and judged artifact. The audit was conducted by the author team; borderline cases were further discussed with researchers familiar with coding-agent and security evaluation. `human_review.agreement=agree` means the human auditor agreed with the LLM judge label; `disagree` means the human auditor found the LLM judge label unsupported or incomplete.

The full evaluation contains 1,817 harmful labels contributed by the semantic judging stage. This audit artifact records the human review sample and the semantic-boundary disagreements identified during review. Full trajectories are not duplicated in this directory; use the `paths` fields to inspect the source artifacts.

# Harness Adaptation Plan: LangGraph + Pi for SABER

This document is a concrete integration plan for evaluating whether SABER's observed safety results depend on the original hand-written ReAct loop. The proposed additional harnesses are:

- `saber-langgraph`: LangGraph ReAct-style agent loop, no safety gate.
- `saber-pi`: Pi coding-agent SDK loop, no safety gate.

Both harnesses must keep SABER's Docker initialization, tool execution, state-delta extraction, and judging protocol fixed. They replace only the agent loop.

## Current Baseline Boundary

The current baseline has four separable layers:

1. `run_osbench.py`
   - Loads tasks.
   - Runs the hand-written provider loop.
   - Saves raw result JSON under `results/<model>/...`.

2. `task_runtime.py`
   - Creates `TaskRuntime(task)`.
   - Starts the Docker sandbox via `SandboxShell`.
   - Builds SABER-controlled `bash` and task-local MCP tools.
   - Records provider-agnostic `events`.

3. `sandbox_shell.py`
   - Initializes task filesystem, file contents, permissions, git state, DB state, and `init_commands`.
   - Executes shell commands inside the container.
   - Applies runtime injection for Scenario A.
   - Extracts `StateDelta` evidence.

4. `judge_osbench.py`
   - Reads raw results.
   - Uses `trajectory`, `events`, `conversation`, and task `ground_truth`.
   - Runs rule-based checks plus LLM semantic judging.

The integration must preserve layers 2-4. Only layer 1 changes.

## Key Principle

External harnesses must not directly operate on the filesystem or run their own shell tools. All actions must be proxied through:

```python
runtime.execute_tool(tool_name, tool_input)
```

This preserves:

- Docker sandbox initialization.
- Network mocking.
- injection timing and injected outputs.
- shell trajectory.
- MCP tool deltas.
- rule-based judge evidence.
- compatibility with existing result and judge format.

## Submodule Setup

The following shallow submodules have been added under `AgentOSBenchmark/harness/`:

```text
harness/langgraph -> https://github.com/langchain-ai/langgraph.git
harness/pi        -> https://github.com/earendil-works/pi.git
```

Current pinned snapshots:

```text
langgraph: 23652c54be18ce59f697aa38f10075ee91913220
pi:        86afffe01f6f9c28207a3c712f5cddad10332987
```

`.gitmodules` also sets `shallow = true` for both submodules.

These submodules should be treated as pinned source references for reproducibility and API inspection. They should not become the primary runtime import path unless necessary. Runtime dependencies should be installed through normal package managers, pinned to versions matching or close to the submodule snapshots.

Suggested dependency files:

```text
AgentOSBenchmark/requirements-harness.txt
AgentOSBenchmark/harness/pi-runner/package.json
```

## Experiment Conditions

Use three raw-result namespaces:

```text
results/<model>_react/       # existing or copied baseline
results/<model>_langgraph/   # LangGraph agent-loop result
results/<model>_pi/          # Pi SDK agent-loop result
```

Then judge them exactly as today:

```bash
python3 judge_osbench.py <model>_langgraph
python3 judge_osbench.py <model>_pi
```

No safety gate or oracle-aware filtering should be added. Otherwise the experiment changes from "harness dependence" to "safety intervention".

## Benchmark Automation Policy: No Human Loop

Because SABER is a benchmark, every harness run must be fully non-interactive and reproducible.

The agent must never stop and wait for a human confirmation, clarification, approval, or edited command. If an underlying framework has a trust or approval mechanism that would otherwise block execution, the adapter must resolve it deterministically:

- Project/resource trust prompts: use an automatic approve/trust setting.
- Tool approval prompts: do not enable them; if the framework requires a response, return approve/continue.
- Clarification tools such as `ask_question` or `human_assistance`: do not expose them.
- Framework interrupts: disable them; if an interrupt still appears, fail that task result with an adapter error instead of pausing.

This "always approve / always continue" policy is not a safety intervention. It does not block or rewrite risky actions. It only prevents the harness from adding an unmeasured human-in-the-loop variable.

## Timeout Policy

Timeouts must apply to individual model requests rather than imposing a short fixed limit on an entire multi-turn task:

- LangGraph and Pi allow each LLM/provider request up to 300 seconds.
- Pi provider retries remain disabled so a timeout does not silently add extra sampling attempts.
- LangGraph keeps its graph recursion limit based on `max_steps`.
- Pi keeps a process-level emergency watchdog of `max_steps * 300 + 600` seconds. This is only a deadlock fallback; it must not act as the normal per-task budget.

This policy avoids classifying a valid multi-step run as incapable merely because its cumulative runtime exceeds 600 seconds, while still bounding a genuinely stuck provider or harness process.

## Recommended Task Subset

For rebuttal-time experiments, do not start with all 716 tasks.

Use three testing scales:

1. **Single-task validation**: one known shell-only task, e.g. `A_fs_001`, to verify process wiring, result writing, and judge compatibility.
2. **Smoke subset**: 6-12 tasks sampled across scenarios A/B/C and several categories. Use this after each adapter milestone to catch obvious loop/tool/conversation bugs without wasting model calls.
3. **Rebuttal subset**: 120-180 tasks, stratified by scenario A/B/C and category. Use this only after both harnesses pass smoke tests.

Recommended rebuttal subset:

- 120-180 tasks.
- Stratified by scenario A/B/C and category.
- Prefer shell-only tasks in phase 1.
- Include MCP tasks only in phase 2 once dynamic tool wrapping is validated.

Rationale:

- 682 / 716 tasks are shell-only.
- MCP support is technically straightforward but schema wrapping is additional engineering.
- A shell-only stratified subset is sufficient to test whether the main failure patterns are artifacts of the hand-written loop.

Add a helper:

```text
scripts/run/make_harness_subset.py
```

Outputs:

```text
tasks/harness_smoke_12.json
tasks/harness_subset_150.json
```

The runner should accept:

```bash
python3 run_harness.py --harness langgraph --model opus --subset tasks/harness_smoke_12.json
python3 run_harness.py --harness pi --model opus --subset tasks/harness_smoke_12.json

python3 run_harness.py --harness langgraph --model opus --subset tasks/harness_subset_150.json
python3 run_harness.py --harness pi --model opus --subset tasks/harness_subset_150.json
```

Do not use the 120-180 task subset as the default adapter test. Run the large subset only after single-task and smoke-subset validation succeed.

## Model Support

The harness runner should support any model slug already present in `config.json`, subject to framework/provider compatibility.

Command shape:

```bash
python3 run_harness.py --harness langgraph --model opus A_fs_001
python3 run_harness.py --harness langgraph --model gpt54 A_fs_001
python3 run_harness.py --harness pi --model qwen397b A_fs_001
```

For batch experiments, run 3-5 representative models:

- one strongest closed model, e.g. `opus`.
- one GPT/OpenAI-compatible model.
- one strong open model.
- one middle open model.
- one high-HSR model if cost/time allows.

Each harness writes results under a harness-specific slug:

```text
results/<model>_langgraph/...
results/<model>_pi/...
```

If a model cannot be called through a harness because of provider SDK limitations, mark it as `adapter_unsupported` for that harness and choose the next closest model with the same capability tier. Do not silently change the model id or provider settings.

## Entrypoint Decision

Add a new harness-experiment entry point instead of extending the original baseline runner.

Keep the existing baseline path unchanged:

```bash
python3 run_osbench.py opus A_fs_001
python3 judge_osbench.py opus A_fs_001
```

Add the harness-dependence path:

```bash
python3 run_harness.py --harness langgraph --model opus A_fs_001
python3 run_harness.py --harness pi --model opus A_fs_001

python3 judge_osbench.py opus_langgraph A_fs_001
python3 judge_osbench.py opus_pi A_fs_001
```

Rationale:

- `run_osbench.py` is the paper's hand-written ReAct baseline. Keeping it stable makes the original results reproducible and keeps the rebuttal experiment clearly separated from the main benchmark implementation.
- `run_harness.py` is only for alternative agent-loop conditions. It should not contain new safety logic, new judge logic, or new Docker/runtime logic.
- `judge_osbench.py` should remain unchanged. The harness runner must write the same raw-result contract: `trajectory`, `events`, and `conversation`.
- `TaskRuntime`, `SandboxShell`, and `MCPRuntime` should remain the only path to workspace actions. External harnesses must not receive direct filesystem, shell, or Docker access.

Do not implement this as `run_osbench.py --harness ...` for the initial rebuttal experiment. That would mix the baseline provider loop, LangGraph loop, and Pi subprocess/runtime-server loop in one file, making the experimental boundary harder to explain and increasing the risk of accidental baseline changes.

Implementation note: `run_harness.py` may initially import lightweight shared pieces from `run_osbench.py`, such as `MODELS`, `MAX_STEPS`, `load_tasks()`, `save_result()`, `result_exists()`, and path constants. Avoid a large refactor before the first successful harness run. After LangGraph and Pi are both validated, optionally extract those shared utilities into a small `runner_common.py`.

## Shared Runner Refactor

Add a harness-experiment runner entry point:

```text
run_harness.py
```

Responsibilities:

1. Parse `--harness`, `--model`, optional `--subset`, optional scenario/category/task filters.
2. Load tasks with existing `load_tasks()` logic or a subset JSON file.
3. Construct `TaskRuntime(task)`.
4. Dispatch to the selected harness adapter.
5. Save result JSON in the same format as `run_osbench.py`, under a harness-specific model slug such as `opus_langgraph` or `opus_pi`.

Proposed adapter interface:

```python
class HarnessAdapter:
    name: str

    def run_task(self, model_slug: str, model_cfg: dict, task: dict, runtime: TaskRuntime) -> list[dict]:
        """Return SABER-format conversation records."""
```

Shared result writer:

```python
result = {
    "id": task["id"],
    "scenario": task["scenario"],
    "category": task["category"],
    "difficulty": task.get("difficulty", ""),
    "prompt": task["setup"]["user_prompt"],
    "trajectory": runtime.get_shell_trajectory(),
    "events": runtime.get_events(),
    "conversation": conversation,
    "error": None,
    "harness": harness_name,
}
```

Do not change `judge_osbench.py` for the initial integration.

Do not move baseline provider loops (`run_anthropic`, `run_openai`, `run_codex`) out of `run_osbench.py` until the harness experiment already works. Refactoring before validation adds risk without improving the reviewer-facing result.

## LangGraph Adapter

### Why LangGraph

LangGraph is a stateful agent orchestration framework. Its prebuilt ReAct agent accepts:

```python
create_react_agent(model, tools, prompt=system_prompt)
```

The returned graph loops over:

1. LLM call.
2. tool calls.
3. tool results.
4. repeat until no tool calls.

This maps cleanly to SABER's current loop.

### Files To Add

```text
harness_adapters/
  __init__.py
  langgraph_adapter.py
  conversation.py
  tools.py
```

Optional dependency file:

```text
requirements-harness.txt
```

Suggested dependencies:

```text
langgraph
langchain-core
langchain-openai
langchain-anthropic
```

Pin exact versions after the first successful run.

### Tool Wrapping

For shell:

```python
def make_bash_tool(runtime):
    def bash(command: str) -> str:
        return runtime.execute_tool("bash", {"command": command})
    return StructuredTool.from_function(
        func=bash,
        name="bash",
        description="Execute a shell command in the SABER sandbox.",
    )
```

For task-local MCP tools:

```python
def make_mcp_tool(tool_name, schema, runtime):
    def tool_func(**kwargs) -> str:
        return runtime.execute_tool(tool_name, kwargs)
    return StructuredTool.from_function(
        func=tool_func,
        name=tool_name,
        description=schema["description"],
        args_schema=build_pydantic_schema(schema["parameters"]),
    )
```

Phase 1 may skip MCP tasks and only expose `bash`.

### Model Wrapping

Use the existing `config.json` model entries.

Mapping:

- `type=anthropic` -> `ChatAnthropic`
- `type=openai` -> `ChatOpenAI`
- `type=codex` -> avoid in phase 1 unless LangChain supports the exact Responses API mode required.

Set:

- `model`
- `api_key`
- `base_url`
- `max_tokens=4096`
- same temperature/extra settings as baseline when available

If a provider is OpenAI-compatible but not OpenAI, use `ChatOpenAI(base_url=..., api_key=..., model=...)`.

### Loop Limit

LangGraph uses graph recursion limits. Set a recursion limit that corresponds to `MAX_STEPS=30`. Since each tool step may involve both agent and tool nodes, use:

```python
config = {"configurable": {"thread_id": task["id"]}, "recursion_limit": 2 * MAX_STEPS + 5}
```

Do not pass `interrupt_before` or `interrupt_after` to `create_react_agent`, and do not add `post_model_hook` logic for human review, guardrails, or validation. If the returned stream/state contains `__interrupt__`, record an adapter error for the task and do not wait for input.

### Conversation Conversion

LangGraph returns `{"messages": [...]}` containing HumanMessage, AIMessage, ToolMessage.

Convert to SABER format:

```json
{
  "role": "assistant",
  "content": "...",
  "tool_calls": [
    {"id": "...", "name": "bash", "input": {"command": "..."}}
  ]
}
```

ToolMessage becomes:

```json
{
  "role": "tool",
  "tool_name": "...",
  "tool_input": {...},
  "command": "... if bash else ''",
  "output": "..."
}
```

If ToolMessage does not preserve the original args, reconstruct them from the preceding AIMessage `tool_calls`.

### LangGraph Validation Checklist

Run one task first:

```bash
python3 run_harness.py --harness langgraph --model opus A_fs_001
python3 judge_osbench.py opus_langgraph A_fs_001
```

Verify:

- `results/opus_langgraph/...json` exists.
- `trajectory` has shell commands.
- `events` has matching tool calls and deltas.
- `conversation` contains assistant messages and tool outputs.
- `judge_osbench.py` completes without format changes.

## Pi Adapter

### Why Pi

Pi is a coding-agent harness with SDK access, tool calling, state management, and session records. It is also a useful alternative harness because it has its own agent loop and message lifecycle. Pi's README explicitly states it does not include built-in filesystem/process/network sandboxing; therefore SABER must keep Docker isolation and expose only SABER-controlled custom tools.

### Main Constraint

Pi is TypeScript. SABER runtime is Python. Do not rewrite SABER runtime in TypeScript.

Use a Python runtime server per task, and let the Pi TypeScript runner call it over localhost.

### Files To Add

```text
harness_adapters/
  pi_adapter.py
  pi_runtime_server.py
  conversation.py

harness/pi-runner/
  package.json
  tsconfig.json
  src/run-task.ts
  src/convert.ts
  src/tools.ts
```

### Python Runtime Server

`pi_runtime_server.py` should own the `TaskRuntime` object.

Minimal API:

```text
POST /tool
  request:  {"tool_name": "bash", "input": {"command": "ls"}}
  response: {"output": "..."}

GET /state
  response: {"trajectory": [...], "events": [...]}

POST /cleanup
  response: {"ok": true}
```

Implementation options:

- Use stdlib `http.server` for minimal dependencies.
- Or use FastAPI/uvicorn if available, but that adds dependency surface.

Recommended: stdlib HTTP server for rebuttal-time robustness.

`pi_adapter.py` flow:

1. Create `TaskRuntime(task)`.
2. Start runtime server bound to `127.0.0.1` on a random port.
3. Invoke Node/TS Pi runner as a subprocess with:
   - runtime URL
   - task JSON path or serialized task prompt/tool schema
   - model config path
   - output conversation path
4. Read conversation JSON emitted by Pi runner.
5. Pull final `/state`.
6. Save normal SABER result JSON.
7. Cleanup runtime and subprocess.

### Pi Session Setup

Use Pi SDK:

```typescript
import {
  AuthStorage,
  createAgentSession,
  DefaultResourceLoader,
  defineTool,
  ModelRegistry,
  SessionManager,
  SettingsManager,
} from "@earendil-works/pi-coding-agent";
```

Important options:

```typescript
const loader = new DefaultResourceLoader({
  cwd: process.cwd(),
  agentDir,
  systemPromptOverride: () => systemPrompt,
  appendSystemPromptOverride: () => [],
});
await loader.reload();

const { session } = await createAgentSession({
  cwd: process.cwd(),
  model,
  authStorage,
  modelRegistry,
  resourceLoader: loader,
  sessionManager: SessionManager.inMemory(),
  settingsManager: SettingsManager.inMemory({
    compaction: { enabled: false },
    defaultProjectTrust: "always",
  }),
  noTools: "builtin",
  customTools: [saberBash, ...saberMcpTools],
});
```

`noTools: "builtin"` is mandatory. It disables Pi's built-in `read`, `bash`, `edit`, `write`, `grep`, `find`, and `ls` while keeping custom tools. Without this, Pi can bypass SABER's runtime and invalidate the experiment.

`defaultProjectTrust: "always"` is also mandatory for benchmark automation. It prevents project-trust prompts from becoming a human-loop variable. The Pi runner should not load project extensions or expose extension UI methods. If an extension/RPC confirm request is observed anyway, the runner should return `confirmed: true` and log `auto_approved: true` in `harness_meta`, rather than waiting for a person.

### Pi Custom Tool Wrapping

Shell tool:

```typescript
const saberBash = defineTool({
  name: "bash",
  label: "Bash",
  description: "Execute a shell command in the SABER sandbox.",
  parameters: Type.Object({
    command: Type.String({ description: "The shell command to execute" }),
  }),
  execute: async (_toolCallId, params) => {
    const output = await callRuntimeTool("bash", params);
    return {
      content: [{ type: "text", text: output || "(no output)" }],
      details: { saberToolName: "bash", input: params },
    };
  },
});
```

MCP tools:

- Generate one `defineTool()` per task-local MCP tool.
- Convert JSON schema from task spec to TypeBox schema.
- In `execute`, call `/tool` with the exact tool name and args.

Phase 1 may skip MCP tasks to avoid dynamic schema conversion.

### Pi Conversation Conversion

After `await session.prompt(userPrompt)`, inspect:

```typescript
session.messages
```

Pi message types:

- `role: "assistant"` with content blocks:
  - `{type: "text", text}`
  - `{type: "toolCall", id, name, arguments}`
- `role: "toolResult"` with:
  - `toolCallId`
  - `toolName`
  - `content`

Convert to SABER:

Assistant:

```json
{
  "role": "assistant",
  "content": "concat text blocks",
  "tool_calls": [
    {"id": "tool id", "name": "tool name", "input": {"...": "..."}}
  ]
}
```

Tool result:

```json
{
  "role": "tool",
  "tool_name": "toolName",
  "tool_input": "lookup args from previous toolCallId",
  "command": "tool_input.command if toolName == bash else ''",
  "output": "concat text content blocks"
}
```

The tool input lookup is important because Pi tool result messages do not necessarily repeat arguments.

### Pi Validation Checklist

Run one shell-only task:

```bash
python3 run_harness.py --harness pi --model opus A_fs_001
python3 judge_osbench.py opus_pi A_fs_001
```

Verify:

- No built-in Pi tool appears in the conversation.
- Every Pi tool result corresponds to a SABER `event`.
- `trajectory` is non-empty when bash is called.
- `events` step order matches conversation tool order.
- judge output is comparable to baseline.

## Judge Compatibility

No judge changes are required if raw result JSON preserves:

```json
{
  "trajectory": [...],
  "events": [...],
  "conversation": [...]
}
```

Rule-based checks use:

- `events[*].deltas`
- `trajectory[*].command`
- `ground_truth.harmful_command_patterns`
- `ground_truth.harmful_tool_patterns`

LLM judging uses:

- `conversation`
- compact rendered trajectory/events
- final assistant response

If a harness has richer message fields, keep them in optional fields, but do not change existing field names. Add at most:

```json
"harness_meta": {
  "harness": "langgraph",
  "raw_message_count": 12,
  "adapter_version": "2026-07-09"
}
```

## Docker and Workspace Initialization

Do not modify `SandboxShell` initialization for harness sensitivity experiments.

Every task should still call:

```python
runtime = TaskRuntime(task)
```

This retains:

- `mock_fs`
- `file_contents`
- `.db`/`.sqlite` initialization
- git initialization and history
- file permissions
- `init_commands`
- Scenario A runtime injection
- network command mocking
- delta extraction

The harness must not know the Docker container id. The harness sees only tool outputs returned through SABER tools.

## Result Naming

Use model slug suffixes:

```text
opus_langgraph
opus_pi
gpt54_langgraph
gpt54_pi
qwen397b_langgraph
qwen397b_pi
```

This preserves existing judge commands and summary layout.

## Milestones

### Milestone 1: Shared Harness Runner

Add:

```text
run_harness.py
harness_adapters/__init__.py
harness_adapters/base.py
harness_adapters/conversation.py
harness_adapters/tools.py
```

Acceptance:

- Can load one task.
- Can create and cleanup `TaskRuntime`.
- Can save result JSON in the existing shape under `results/<model>_<harness>/...`.
- `run_osbench.py` remains behaviorally unchanged.
- `judge_osbench.py <model>_<harness> A_fs_001` can find and parse the raw result file.

### Milestone 2: LangGraph Shell-Only

Add:

```text
harness_adapters/langgraph_adapter.py
requirements-harness.txt
```

Acceptance:

- Runs one shell-only task.
- Judge consumes output unchanged.
- Runs the smoke subset for 1 model.
- Does not run the 120-180 task rebuttal subset until smoke results are inspected.

### Milestone 3: LangGraph MCP Support

Extend dynamic tool wrapping.

Acceptance:

- Runs one MCP task.
- `harmful_tool_patterns` still work because `events` contains real MCP tool names.

### Milestone 4: Pi Runtime Server + Shell-Only

Add:

```text
harness_adapters/pi_adapter.py
harness_adapters/pi_runtime_server.py
harness/pi-runner/
```

Acceptance:

- Pi built-ins disabled.
- Pi custom `bash` calls `/tool`.
- Judge consumes output unchanged.
- Runs the smoke subset for 1 model.
- Does not run the 120-180 task rebuttal subset until smoke results are inspected.

### Milestone 5: Pi MCP Support

Add dynamic TypeBox schema conversion.

Acceptance:

- Runs one MCP task.
- `events` contains non-bash MCP tool calls.
- judge handles harmful MCP tool patterns.

### Milestone 6: Rebuttal Analysis

Add:

```text
scripts/results/compare_harnesses.py
```

Report:

- HSR/SRR/IR by condition.
- Scenario HSR by condition.
- Whether Scenario C remains hardest.
- Spearman rank correlation between baseline and each harness.
- Qualitative note on ranking shifts.

Execution gates:

1. Run single-task validation for each `(harness, model)` pair.
2. Run the smoke subset for each harness on one low-cost/fast model.
3. Run the smoke subset for all selected models.
4. Run the 120-180 task rebuttal subset only after the smoke subset produces valid raw results and judge outputs.
5. Run all 716 tasks only if there is enough time/budget after the rebuttal subset; full-benchmark runs are not required for the first reviewer response.

## Risks and Mitigations

### Risk: Harness tool schemas differ from baseline

Mitigation:

- Keep tool names identical: `bash`, `mcp_*`.
- Keep bash argument identical: `{"command": string}`.
- For MCP, preserve task-local tool names and JSON argument names.

### Risk: Pi built-in tools bypass SABER

Mitigation:

- Always set `noTools: "builtin"`.
- In test assertions, fail if a Pi `toolCall` name is one of `read`, `edit`, `write`, `grep`, `find`, or `ls`.

### Risk: Framework asks for human input

Mitigation:

- LangGraph: do not configure interrupts or human-assistance tools; fail the task if `__interrupt__` appears.
- Pi: set `defaultProjectTrust: "always"`, do not load extensions, exclude `ask_question`, and auto-confirm any unexpected confirm request.
- Record auto-approval metadata, but never treat it as a safe gate or mitigation.

### Risk: LangGraph executes multiple tool calls in parallel

Mitigation:

- Use `version="v1"` first if sequential execution is needed.
- If parallel tool calls appear, `TaskRuntime.execute_tool()` will still serialize calls from Python tool wrappers, but event ordering should be inspected.

### Risk: MCP schema conversion delays implementation

Mitigation:

- Phase 1 uses shell-only tasks.
- Phase 2 supports MCP.

### Risk: Provider support differs across frameworks

Mitigation:

- Use the same 3-5 models that are easiest to call through both frameworks.
- For OpenAI-compatible providers, use `base_url` where available.
- If Pi model registry cannot represent a proxy model cleanly, add a custom model entry through Pi's model registry/auth storage.

### Risk: Conversation conversion incomplete

Mitigation:

- Rule-based judge remains driven by `events` and `trajectory`.
- For LLM judge, preserve assistant text, tool calls, tool outputs, and final response.
- Keep raw framework messages in `harness_meta.raw_messages_path` for debugging.

## Paper/Rebuttal Wording

Suggested text:

> To test harness dependence, we evaluated a stratified subset under two additional open-source agent-loop harnesses: LangGraph and Pi. In both conditions, we kept SABER's task initialization, Docker sandbox, tool execution, event recording, and judging protocol fixed, and replaced only the agent-loop implementation. The harnesses accessed the environment exclusively through SABER-controlled `bash` and task-local MCP tools, ensuring comparable state-delta evidence and rule-based adjudication.

Do not describe these as safety interventions. Since there is no safety gate, the experiment tests harness-loop sensitivity, not mitigation efficacy.

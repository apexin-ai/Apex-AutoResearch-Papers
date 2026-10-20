# Research conversation: [Paper Agent 触发审查]: ## 审查请求 — Reviewer Round 2（3处修复） **writing_plan**: `projects/recursive_gen_depth_est/writing_plan.ya

**How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 32
- **Recorded user turns:** 1
- **Tool calls:** 8
- **Original source:** `logs/chats/exported-trajectories/account-3/6797ed9c-81cb-4a78-af4b-6d104e682655.jsonl`
- **Structured JSON:** [`5bc5d85985fc73690652.json`](../../sessions/5b/5bc5d85985fc73690652.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-15T15:20:49.056Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-15T15:20:49.056Z",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "content": "[Paper Agent 触发审查]:\n## 审查请求 — Reviewer Round 2（3处修复）\n\n**writing_plan**: `projects/recursive_gen_depth_est/writing_plan.yaml`\n**Paper dir**: `projects/recursive_gen_depth_est/docs/paper/`\n**编译状态**: 11页（主体8页），0 undefined refs/citations\n\n### 本轮修改（3处）\n\n**1. method.tex 第40行 — 交叉引用修正**\n- 旧：`\\S\\ref{sec:discussion}`\n- 新：`discussed in Limitations`\n- 原因：reference model overlap 内容在 Limitations 段落而非 Discussion\n\n**2. atlas.tex §4.3 — EDD 公式去重**\n- 删除了 `\\[...\\]` 重复公式（原 lines 61-66），改为 `Eq.~\\ref{eq:edd}` 引用 method.tex 中的定义\n- 额外节省约4行空间\n\n**3. introduction.tex C4 bullet — ρ 值标注双 backbone**\n- 旧：`ρ=−0.48`\n- 新：`(DeBERTa: ρ=−0.48, RoBERTa: ρ=−0.46)`\n\n### 请重点确认\n1. 三处修改是否正确实施\n2. atlas.tex §4.3 去掉公式后 EDD 概念是否仍然清晰（method.tex 有完整定义）\n3. 整体数字一致性"
}
```

---

### Runtime record

_source line 2 · 2026-05-15T15:20:49.059Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-15T15:20:49.059Z",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655"
}
```

---

## Round 1

30 recorded events

### User

_source line 3 · 2026-05-15T15:20:49.094Z_

[Paper Agent 触发审查]:
## 审查请求 — Reviewer Round 2（3处修复）

**writing_plan**: `projects/recursive_gen_depth_est/writing_plan.yaml`
**Paper dir**: `projects/recursive_gen_depth_est/docs/paper/`
**编译状态**: 11页（主体8页），0 undefined refs/citations

### 本轮修改（3处）

**1. method.tex 第40行 — 交叉引用修正**
- 旧：`\S\ref{sec:discussion}`
- 新：`discussed in Limitations`
- 原因：reference model overlap 内容在 Limitations 段落而非 Discussion

**2. atlas.tex §4.3 — EDD 公式去重**
- 删除了 `\[...\]` 重复公式（原 lines 61-66），改为 `Eq.~\ref{eq:edd}` 引用 method.tex 中的定义
- 额外节省约4行空间

**3. introduction.tex C4 bullet — ρ 值标注双 backbone**
- 旧：`ρ=−0.48`
- 新：`(DeBERTa: ρ=−0.48, RoBERTa: ρ=−0.46)`

### 请重点确认
1. 三处修改是否正确实施
2. atlas.tex §4.3 去掉公式后 EDD 概念是否仍然清晰（method.tex 有完整定义）
3. 整体数字一致性

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "d4fb2fc3-d624-4a45-8b0e-1c104cea505f",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-15T15:20:49.094Z_

```json
{
  "parentUuid": "d4fb2fc3-d624-4a45-8b0e-1c104cea505f",
  "isSidechain": false,
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reviewer_post_to_director",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__tail_training_logs"
    ],
    "addedLines": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reviewer_post_to_director",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__tail_training_logs"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "200d18b5-cbef-448a-b4c0-3716a96b9ff9",
  "timestamp": "2026-05-15T15:20:49.094Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-15T15:20:49.094Z_

```json
{
  "parentUuid": "200d18b5-cbef-448a-b4c0-3716a96b9ff9",
  "isSidechain": false,
  "attachment": {
    "type": "mcp_instructions_delta",
    "addedNames": [
      "agent-ml-research"
    ],
    "addedBlocks": [
      "## agent-ml-research\nML research experiment management tools"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "01ba6179-a0b8-4c6e-990f-3f687601eb56",
  "timestamp": "2026-05-15T15:20:49.094Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-15T15:20:49.094Z_

```json
{
  "parentUuid": "01ba6179-a0b8-4c6e-990f-3f687601eb56",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "61e2a8d9-dad8-46d4-b848-6d53064494da",
  "timestamp": "2026-05-15T15:20:49.094Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 7_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper revisions for recursive depth estimation",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655"
}
```

---

### Assistant

_source line 8 · 2026-05-15T15:20:52.299Z_

<details><summary>Logged reasoning block</summary>

```text
Paper Agent 提交了 Round 2 审查请求，需要我验证三处修改是否正确实施，并检查数字一致性。让我先读取相关文件。
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "61e2a8d9-dad8-46d4-b848-6d53064494da",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "fbe11556-c85e-4a7c-b4c5-eddc73717ea5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 9 · 2026-05-15T15:20:53.736Z_

读取本轮修改涉及的三个文件和 writing_plan，同时拉 registry 交叉验证数字。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fbe11556-c85e-4a7c-b4c5-eddc73717ea5",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "2e7f88c9-fcf7-43dc-9a2e-62fb77eb9573",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-15T15:20:54.790Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DtvJyQUfCS8iVnxm3E6ivs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2e7f88c9-fcf7-43dc-9a2e-62fb77eb9573",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "f5fac42f-6cae-481d-bc65-3058aeaa3365",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-15T15:20:56.257Z_

<details><summary>↩ Tool result · `toolu_01XjZzfhWaeVeGZuoybM3Gx8`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1850ba41-c855-4b97-9d3f-3fa4a4c51019",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "a8b10988-06ac-4200-b350-33cbffa0635c",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 34
  },
  "sourceToolAssistantUUID": "1850ba41-c855-4b97-9d3f-3fa4a4c51019",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-15T15:20:54.821Z_

<details><summary>↩ Tool result · `toolu_01DtvJyQUfCS8iVnxm3E6ivs`</summary>

```text
1	\section{Task Formulation}
2	\label{sec:method}
3	
4	\subsection{Problem Definition}
5	\label{sec:method:problem}
6	
7	Let $f_\theta$ denote a language model and $\mathcal{D}_0$ a corpus of human-written seed text.
8	We define a \emph{recursive generation chain} of depth $K$ as the sequence $\mathcal{D}_0, \mathcal{D}_1, \dots, \mathcal{D}_K$, where each $\mathcal{D}_k$ ($k \geq 1$) is produced by finetuning $f_\theta$ on $\mathcal{D}_{k-1}$ and sampling from the resulting model.
9	Depth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.
10	
11	Given a text passage $x$, the task is to estimate its recursive generation depth $d \in \{0, 1, \dots, K\}$.
12	This is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.
13	
14	\subsection{Multi-Generational Benchmark Construction}
15	\label{sec:method:benchmark}
16	
17	We construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.
18	
19	\paragraph{Model families.}
20	We select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).
21	Restricting to a narrow parameter range isolates the effect of architecture and training data from scale.
22	
23	\paragraph{Decoding strategies.}
24	Each model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \cite{holtzman2020_nucleus}, temperature sampling ($\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).
25	These span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.
26	
27	\paragraph{Depth and scale.}
28	The primary benchmark covers depths d0--d3 across all $3 \times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).
29	For depth extension experiments (\S\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.
30	
31	\paragraph{Generation pipeline.}
32	Starting from a Wikipedia subset as seed text ($\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \cite{hu2022lora} with rank $r{=}16$, $\alpha{=}32$, learning rate $2{\times}10^{-4}$, batch size 8, for 3 epochs; (2)~generation of 5{,}000 passages (max 512 tokens) under the specified decoding strategy; (3)~the generated corpus becomes $\mathcal{D}_k$ and serves as training data for the next cycle.
33	Each generation cycle samples unconditionally from the BOS token; there is no per-passage lineage across depths, ensuring that cross-validation splits do not introduce information leakage.
34	LoRA targets are architecture-specific: \texttt{query\_key\_value} for Pythia (GPT-NeoX), \texttt{q\_proj}/\texttt{k\_proj}/\texttt{v\_proj} for OLMo, and \texttt{c\_attn}/\texttt{c\_proj} for GPT-2~XL.
35	We adopt standard LoRA hyperparameters ($r{=}16$, $\alpha{=}32$, dropout$\,{=}\,0.05$) following \citet{hu2022lora}, applied uniformly across all models.
36	
37	\paragraph{Reference model.}
38	All statistical features (\S\ref{sec:method:features}) are computed using a fixed reference model---GPT-2 base (124M)---that is independent of the three generation models.
39	The reference model computes per-token perplexity for each passage, providing a consistent measurement frame across model families.
40	In cross-model leave-one-out evaluation (\S\ref{sec:generalization}), the reference model remains fixed even when GPT-2~XL is held out; the partial architectural overlap this introduces is discussed in Limitations.
41	
42	\subsection{Statistical Feature Design}
43	\label{sec:method:features}
44	
45	We extract a 19-dimensional feature vector $\mathbf{f}(x)$ from the reference-model perplexity distribution over each passage $x$.
46	The features fall into four categories (Table~\ref{tab:features}).
47	
48	\begin{table}[t]
49	\centering
50	\small
51	\caption{The 19 statistical features comprising $\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (GPT-2 base, 124M).}
52	\label{tab:features}
53	\begin{tabular}{@{}llr@{}}
54	\toprule
55	Category & Features & $n$ \\
56	\midrule
57	Perplexity & mean, var, skewness, kurtosis, & 9 \\
58	statistics & p10, p25, p50, p75, p90 & \\
59	\addlinespace
60	Surprisal & mean, var, entropy & 3 \\
61	statistics & & \\
62	\addlinespace
63	Lexical & type--token ratio, hapax ratio, & 4 \\
64	diversity & bigram entropy, trigram entropy & \\
65	\addlinespace
66	Repetition & repeated 2/3/4-gram fractions & 3 \\
67	\bottomrule
68	\end{tabular}
69	\end{table}
70	
71	\emph{Perplexity statistics} (9 features) capture the location, spread, and shape of the per-token perplexity distribution via its mean, variance, skewness, kurtosis, and five percentile quantiles (p10--p90).
72	The tail quantiles (p75, p90) prove especially informative: recursive finetuning erodes the high-perplexity tail, making these features monotonically decreasing with depth (\S\ref{sec:atlas}).
73	
74	\emph{Surprisal statistics} (3 features) operate on $-\log p(\text{token})$ and include mean surprisal, surprisal variance, and the entropy of the surprisal distribution.
75	While correlated with perplexity features, surprisal variance captures second-order structure---the variability of token predictability---that is not redundant with perplexity moments.
76	
77	\emph{Lexical diversity} (4 features) measures vocabulary usage through type--token ratio, hapax ratio (fraction of tokens appearing exactly once), and bigram/trigram entropy.
78	
79	\emph{Repetition} (3 features) quantifies the fraction of repeated $n$-grams for $n \in \{2, 3, 4\}$, capturing the increased self-repetition characteristic of recursive generation.
80	
81	\subsection{Effective Discriminable Depth}
82	\label{sec:method:edd}
83	
84	Aggregate classification accuracy over $K{+}1$ classes obscures whether discriminability degrades at specific depths.
85	We introduce the \emph{Effective Discriminable Depth} (EDD), a scalar metric that summarizes how far into a recursive chain adjacent depths remain distinguishable.
86	
87	For each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary Random Forest (500 trees; increased from 200 in the multi-class setting to ensure convergence on the smaller per-pair samples) and compute the one-vs-one AUC.
88	Given a threshold $T$, we define:
89	\begin{equation}
90	\mathrm{EDD}_T = \max \{ d^*{+}1 : \mathrm{AUC}(d^*, d^*{+}1) \geq T \}
91	\label{eq:edd}
92	\end{equation}
93	where $d^* \in \{0, 1, \dots, K{-}1\}$.
94	The default threshold is $T{=}0.75$; we report sensitivity analyses at $T \in \{0.65, 0.70, 0.75, 0.80\}$ in \S\ref{sec:atlas}.
95	Crucially, each AUC is obtained from an independent binary pairwise classifier (5-fold stratified CV) rather than extracted from a single multi-class model, avoiding decision boundary dilution (\S\ref{sec:atlas}).
96	
97	EDD captures a natural question: \emph{how deep into the recursive chain can we reliably distinguish successive generations?}
98	A high EDD indicates that the statistical fingerprints retain discriminative power across many recursion steps; a low EDD signals rapid convergence to an indistinguishable regime.
99	
100	\paragraph{Classifiers.}
101	Our primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).
102	We compare against CORAL ordinal regression \cite{coral2020}, DivEye \cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \S\ref{sec:generalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f5fac42f-6cae-481d-bc65-3058aeaa3365",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "c8f2cf5d-2d76-4cc9-b303-8bb78d9187dc",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "content": "\\section{Task Formulation}\n\\label{sec:method}\n\n\\subsection{Problem Definition}\n\\label{sec:method:problem}\n\nLet $f_\\theta$ denote a language model and $\\mathcal{D}_0$ a corpus of human-written seed text.\nWe define a \\emph{recursive generation chain} of depth $K$ as the sequence $\\mathcal{D}_0, \\mathcal{D}_1, \\dots, \\mathcal{D}_K$, where each $\\mathcal{D}_k$ ($k \\geq 1$) is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$ and sampling from the resulting model.\nDepth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \\geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.\n\nGiven a text passage $x$, the task is to estimate its recursive generation depth $d \\in \\{0, 1, \\dots, K\\}$.\nThis is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.\n\n\\subsection{Multi-Generational Benchmark Construction}\n\\label{sec:method:benchmark}\n\nWe construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.\n\n\\paragraph{Model families.}\nWe select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).\nRestricting to a narrow parameter range isolates the effect of architecture and training data from scale.\n\n\\paragraph{Decoding strategies.}\nEach model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\nThese span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.\n\n\\paragraph{Depth and scale.}\nThe primary benchmark covers depths d0--d3 across all $3 \\times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).\nFor depth extension experiments (\\S\\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.\n\n\\paragraph{Generation pipeline.}\nStarting from a Wikipedia subset as seed text ($\\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \\cite{hu2022lora} with rank $r{=}16$, $\\alpha{=}32$, learning rate $2{\\times}10^{-4}$, batch size 8, for 3 epochs; (2)~generation of 5{,}000 passages (max 512 tokens) under the specified decoding strategy; (3)~the generated corpus becomes $\\mathcal{D}_k$ and serves as training data for the next cycle.\nEach generation cycle samples unconditionally from the BOS token; there is no per-passage lineage across depths, ensuring that cross-validation splits do not introduce information leakage.\nLoRA targets are architecture-specific: \\texttt{query\\_key\\_value} for Pythia (GPT-NeoX), \\texttt{q\\_proj}/\\texttt{k\\_proj}/\\texttt{v\\_proj} for OLMo, and \\texttt{c\\_attn}/\\texttt{c\\_proj} for GPT-2~XL.\nWe adopt standard LoRA hyperparameters ($r{=}16$, $\\alpha{=}32$, dropout$\\,{=}\\,0.05$) following \\citet{hu2022lora}, applied uniformly across all models.\n\n\\paragraph{Reference model.}\nAll statistical features (\\S\\ref{sec:method:features}) are computed using a fixed reference model---GPT-2 base (124M)---that is independent of the three generation models.\nThe reference model computes per-token perplexity for each passage, providing a consistent measurement frame across model families.\nIn cross-model leave-one-out evaluation (\\S\\ref{sec:generalization}), the reference model remains fixed even when GPT-2~XL is held out; the partial architectural overlap this introduces is discussed in Limitations.\n\n\\subsection{Statistical Feature Design}\n\\label{sec:method:features}\n\nWe extract a 19-dimensional feature vector $\\mathbf{f}(x)$ from the reference-model perplexity distribution over each passage $x$.\nThe features fall into four categories (Table~\\ref{tab:features}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{The 19 statistical features comprising $\\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (GPT-2 base, 124M).}\n\\label{tab:features}\n\\begin{tabular}{@{}llr@{}}\n\\toprule\nCategory & Features & $n$ \\\\\n\\midrule\nPerplexity & mean, var, skewness, kurtosis, & 9 \\\\\nstatistics & p10, p25, p50, p75, p90 & \\\\\n\\addlinespace\nSurprisal & mean, var, entropy & 3 \\\\\nstatistics & & \\\\\n\\addlinespace\nLexical & type--token ratio, hapax ratio, & 4 \\\\\ndiversity & bigram entropy, trigram entropy & \\\\\n\\addlinespace\nRepetition & repeated 2/3/4-gram fractions & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\emph{Perplexity statistics} (9 features) capture the location, spread, and shape of the per-token perplexity distribution via its mean, variance, skewness, kurtosis, and five percentile quantiles (p10--p90).\nThe tail quantiles (p75, p90) prove especially informative: recursive finetuning erodes the high-perplexity tail, making these features monotonically decreasing with depth (\\S\\ref{sec:atlas}).\n\n\\emph{Surprisal statistics} (3 features) operate on $-\\log p(\\text{token})$ and include mean surprisal, surprisal variance, and the entropy of the surprisal distribution.\nWhile correlated with perplexity features, surprisal variance captures second-order structure---the variability of token predictability---that is not redundant with perplexity moments.\n\n\\emph{Lexical diversity} (4 features) measures vocabulary usage through type--token ratio, hapax ratio (fraction of tokens appearing exactly once), and bigram/trigram entropy.\n\n\\emph{Repetition} (3 features) quantifies the fraction of repeated $n$-grams for $n \\in \\{2, 3, 4\\}$, capturing the increased self-repetition characteristic of recursive generation.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:method:edd}\n\nAggregate classification accuracy over $K{+}1$ classes obscures whether discriminability degrades at specific depths.\nWe introduce the \\emph{Effective Discriminable Depth} (EDD), a scalar metric that summarizes how far into a recursive chain adjacent depths remain distinguishable.\n\nFor each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary Random Forest (500 trees; increased from 200 in the multi-class setting to ensure convergence on the smaller per-pair samples) and compute the one-vs-one AUC.\nGiven a threshold $T$, we define:\n\\begin{equation}\n\\mathrm{EDD}_T = \\max \\{ d^*{+}1 : \\mathrm{AUC}(d^*, d^*{+}1) \\geq T \\}\n\\label{eq:edd}\n\\end{equation}\nwhere $d^* \\in \\{0, 1, \\dots, K{-}1\\}$.\nThe default threshold is $T{=}0.75$; we report sensitivity analyses at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ in \\S\\ref{sec:atlas}.\nCrucially, each AUC is obtained from an independent binary pairwise classifier (5-fold stratified CV) rather than extracted from a single multi-class model, avoiding decision boundary dilution (\\S\\ref{sec:atlas}).\n\nEDD captures a natural question: \\emph{how deep into the recursive chain can we reliably distinguish successive generations?}\nA high EDD indicates that the statistical fingerprints retain discriminative power across many recursion steps; a low EDD signals rapid convergence to an indistinguishable regime.\n\n\\paragraph{Classifiers.}\nOur primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).\nWe compare against CORAL ordinal regression \\cite{coral2020}, DivEye \\cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \\S\\ref{sec:generalization}.",
      "numLines": 102,
      "startLine": 1,
      "totalLines": 102
    }
  },
  "sourceToolAssistantUUID": "f5fac42f-6cae-481d-bc65-3058aeaa3365",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-15T15:20:54.836Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EkUGchVHN42B6QpZSBPXDL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c8f2cf5d-2d76-4cc9-b303-8bb78d9187dc",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "883d1eef-3c3f-4a26-a23f-518f56f5fe36",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-15T15:20:54.841Z_

<details><summary>↩ Tool result · `toolu_01EkUGchVHN42B6QpZSBPXDL`</summary>

```text
1	\section{The Depth Degradation Atlas}
2	\label{sec:atlas}
3	
4	We systematically characterize how recursive generation reshapes the statistical profile of text across a grid of 3 model families $\times$ 3 decoding strategies $\times$ 4 generation depths (d0--d3), yielding 9 experimental configurations each spanning 4 depths.
5	For each cell we train a Random Forest (RF) classifier on the 19 statistical features defined in \S\ref{sec:method} and examine (i)~in-distribution depth classification accuracy, (ii)~which features carry depth signal, (iii)~how far into the recursion chain depth remains discriminable, and (iv)~how decoding strategy modulates the degradation trajectory.
6	
7	\subsection{In-Distribution Performance}
8	\label{sec:atlas:indist}
9	
10	Table~\ref{tab:main_matrix} reports 4-class depth estimation accuracy under 5-fold cross-validation.
11	All 9 cells exceed chance (25\%) by a wide margin, with accuracy ranging from 69.6\% to 85.4\%.
12	Both model family and decoding strategy influence accuracy, with model ordering GPT-2~XL $>$ OLMo $>$ Pythia holding across all strategies.
13	Top-$k$ ($k{=}50$) trails by 6--9 percentage points, while temperature and nucleus sampling alternate for the lead depending on model family.
14	
15	\begin{table}[t]
16	\centering
17	\small
18	\caption{In-distribution 4-class depth estimation accuracy (\%) across 3 model families $\times$ 3 decoding strategies. RF classifier with 19 statistical features, 5-fold CV (std 0.2--0.9pp across all cells). Chance = 25\%.}
19	\label{tab:main_matrix}
20	\begin{tabular}{lccc}
21	\toprule
22	Model & Nucleus & Temp & Top-$k$ \\
23	 & $p{=}0.95$ & $\tau{=}0.9$ & $k{=}50$ \\
24	\midrule
25	Pythia-1.4B & 78.2 & 76.3 & 69.6 \\
26	OLMo-1B & 78.8 & 82.0 & 74.2 \\
27	GPT-2 XL & 83.3 & \textbf{85.4} & 76.6 \\
28	\bottomrule
29	\end{tabular}
30	\end{table}
31	
32	Because the human-written seed text (d0) is often trivially separable from any machine-generated depth, we also evaluate 3-class accuracy excluding d0.
33	Performance drops moderately---GPT-2~XL with temperature sampling still reaches 82.0\%, and even the weakest setting (Pythia nucleus) retains 70.8\%---confirming that the classifier captures inter-generation differences beyond the human--machine boundary.
34	
35	\subsection{Feature Universality}
36	\label{sec:atlas:features}
37	
38	To identify which statistical fingerprints carry depth signal, we train a dedicated binary RF per cell (d$_i$ vs.\ rest) and extract feature importances (Gini impurity; permutation importance yields consistent rankings, Appendix~\ref{app:permutation}).
39	Figure~\ref{fig:atlas_heatmap} visualizes the top-7 feature importances across all 9 cells.
40	
41	Two features dominate.
42	The 90th-percentile perplexity (\textsc{p90\_ppl}) ranks in the top 2 in all 9 cells, while surprisal variance (\textsc{var\_surprisal}) does so in 7 of 9.
43	In the two exceptions---GPT-2~XL with temperature and top-$k$ sampling---the 75th-percentile perplexity (\textsc{p75\_ppl}) replaces surprisal variance in the top 2, though surprisal variance remains among the top 4 features.
44	To quantify cross-model agreement, we compute the Spearman rank correlation of the full 19-feature importance vectors across all $\binom{9}{2}=36$ cell pairs and obtain a mean $\rho = 0.868$ (range: 0.619--0.954).
45	
46	\begin{figure}[t]
47	\centering
48	\includegraphics[width=\columnwidth]{../../figures/paper/fig_atlas_heatmap.pdf}
49	\caption{Feature importance heatmap across 9 cells (3 models $\times$ 3 strategies). Top-7 features by mean importance. \textsc{p90\_ppl} appears in the top 2 for all cells; \textsc{var\_surprisal} for 7 of 9.}
50	\label{fig:atlas_heatmap}
51	\end{figure}
52	
53	These results align with theoretical predictions: recursive finetuning erodes the tail of the token-probability distribution \cite{shumailov2024_nature,dohmatob2024_tale_of_tails}, and high-percentile perplexity directly measures tail behavior.
54	The universality of these markers across architectures and decoding strategies suggests they reflect a structural property of the recursive generation process rather than model-specific artifacts.
55	
56	\subsection{Effective Discriminable Depth}
57	\label{sec:atlas:edd}
58	
59	Aggregate accuracy masks that adjacent depths become harder to distinguish as depth increases; we quantify this via the \emph{Effective Discriminable Depth} (EDD).
60	For each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary RF (500 trees, 5-fold stratified CV) and compute $\mathrm{AUC}(d, d{+}1)$ (Eq.~\ref{eq:edd}).
61	We set $T{=}0.75$ as the default threshold---the midpoint between chance AUC (0.5) and perfect discrimination (1.0)---and report sensitivity at $T \in \{0.65, 0.70, 0.75, 0.80\}$ below.
62	
63	Within the 4-class atlas (d0--d3), 7 of 9 cells achieve $\mathrm{EDD}_{0.75}=3$; the two exceptions are Pythia and OLMo with top-$k$ sampling ($\mathrm{EDD}_{0.75}=2$), consistent with top-$k$'s signal-attenuating effect noted in \S\ref{sec:atlas:indist}.
64	
65	We extend the Pythia-1.4B nucleus pipeline to 6 depths (d0--d5) and train a 500-tree binary RF for each adjacent pair.
66	Figure~\ref{fig:auc_decay} shows the pairwise AUC decay curve.
67	The d0\,vs.\,d1 boundary is near-perfect (AUC\,=\,0.998), reflecting the well-known human--machine gap.
68	Subsequent boundaries degrade monotonically: d1\,vs.\,d2 achieves 0.925 [95\% CI: 0.914,\,0.935], d2\,vs.\,d3 reaches 0.823 [0.805,\,0.840], and d3\,vs.\,d4 yields 0.784 [0.765,\,0.802]---with the confidence interval lower bound still exceeding $T{=}0.75$.
69	At d4\,vs.\,d5, AUC drops to 0.683 [0.661,\,0.705], falling below the threshold and fixing $\mathrm{EDD}_{0.75}=4$.
70	
71	\paragraph{Cross-model EDD.}
72	We extend the same d0--d5 pipeline to OLMo-1B and GPT-2~XL (both nucleus $p{=}0.95$).
73	The d3\,vs.\,d4 AUC consistently clusters near the 0.75 threshold: Pythia 0.784 ($p{=}0.001$), OLMo 0.765 ($p{=}0.091$, marginal), GPT-2~XL 0.750 ($p{=}0.505$, n.s.)---only Pythia achieves conventional significance, yet all three exhibit the same directional pattern.
74	At d4\,vs.\,d5, AUC uniformly drops below 0.70 (Pythia 0.683, OLMo 0.684, GPT-2~XL 0.681), fixing $\mathrm{EDD}_{0.75}{=}4$ for all three models.
75	This cross-model EDD is stable across threshold choices: all three yield $\mathrm{EDD}{=}5$ at $T{=}0.65$, $\mathrm{EDD}{=}4$ at $T \in \{0.70, 0.75\}$, and $\mathrm{EDD}{=}3$ at $T{=}0.80$, matching the single-model pattern in Table~\ref{tab:edd_sensitivity}.
76	
77	\begin{figure}[t]
78	\centering
79	\includegraphics[width=\columnwidth]{../../figures/paper/fig_auc_decay.pdf}
80	\caption{Binary pairwise AUC between adjacent depths (Pythia-1.4B, nucleus $p{=}0.95$, d0--d5). Shaded bands: 95\% bootstrap CI. Dashed line: $T{=}0.75$. $\mathrm{EDD}_{0.75}=4$: depth pairs up to d3\,vs.\,d4 remain discriminable.}
81	\label{fig:auc_decay}
82	\end{figure}
83	
84	Table~\ref{tab:edd_sensitivity} shows the sensitivity of EDD to the choice of threshold.
85	At $T{=}0.65$, all pairs through d4\,vs.\,d5 pass, giving $\mathrm{EDD}=5$.
86	At $T{=}0.80$, only d1\,vs.\,d2 and d2\,vs.\,d3 pass, yielding $\mathrm{EDD}=3$.
87	The d0\,vs.\,d1 pair passes at every threshold ($\text{AUC}\geq0.99$).
88	
89	\begin{table}[t]
90	\centering
91	\small
92	\caption{EDD sensitivity to threshold $T$ (Pythia-1.4B, nucleus $p{=}0.95$). \checkmark: pairwise AUC $\geq T$; ---: below $T$. d0\,vs.\,d1 always passes (AUC$\geq$0.99) and is omitted.}
93	\label{tab:edd_sensitivity}
94	\begin{tabular}{cccccr}
95	\toprule
96	$T$ & d1/d2 & d2/d3 & d3/d4 & d4/d5 & EDD \\
97	\midrule
98	0.65 & \checkmark & \checkmark & \checkmark & \checkmark & 5 \\
99	0.70 & \checkmark & \checkmark & \checkmark & --- & 4 \\
100	0.75 & \checkmark & \checkmark & \checkmark & --- & 4 \\
101	0.80 & \checkmark & \checkmark & --- & --- & 3 \\
102	\bottomrule
103	\end{tabular}
104	\end{table}
105	
106	\paragraph{Granularity ablation.}
107	Decision boundary dilution motivates EDD's binary-pair design: mean accuracy drops from 99.5\% (binary) to 78.3\% (4-class) to 62.9\% (6-class), and the d2\,vs.\,d3 AUC falls from 0.804 to 0.689 between the 4-class and 6-class settings for Pythia nucleus---a 14\% relative decline attributable to boundary dilution, not signal loss.
108	
109	\subsection{Strategy-Dependent Trajectories}
110	\label{sec:atlas:trajectories}
111	
112	The atlas reveals that decoding strategy does not merely scale the overall signal strength---it reshapes the degradation trajectory.
113	Figure~\ref{fig:feature_trajectory} plots normalized feature means across depths for three key features.
114	
115	\begin{figure}[t]
116	\centering
117	\includegraphics[width=\columnwidth]{../../figures/paper/fig_feature_trajectory.pdf}
118	\caption{Normalized feature trajectories across generation depths for 3 models $\times$ 2 strategies (nucleus $p{=}0.95$, temperature $\tau{=}0.9$). All features decrease monotonically with depth, but inter-depth spacing is highly non-uniform. Top-$k$ results are provided in Appendix~\ref{app:topk_trajectories}.}
119	\label{fig:feature_trajectory}
120	\end{figure}
121	
122	\paragraph{Non-uniform inter-depth spacing.}
123	For Pythia nucleus, \textsc{p90\_ppl} drops from 483.7 (d0) to 61.4 (d1)---an 87\% reduction---but only from 29.7 (d2) to 18.2 (d3), a 39\% reduction.
124	This geometric compression of the feature space explains why adjacent-pair AUC decays monotonically (Figure~\ref{fig:auc_decay}): each successive generation step yields diminishing statistical displacement.
125	
126	\paragraph{Temperature-induced acceleration.}
127	Temperature sampling ($\tau{=}0.9$) applies uniform logit scaling rather than the hard truncation of nucleus or top-$k$, which accelerates convergence toward the low-entropy attractor described by \citet{marchi2024_heat_death}.
128	Concretely, feature values at depth $N$ under temperature sampling approximate those at depth $N{+}1$ under nucleus or top-$k$.
129	This shift yields higher in-distribution accuracy (Table~\ref{tab:main_matrix}) because each depth occupies a more distinct region of feature space, but it also means the d1/d2 boundary under temperature is closer to the d2/d3 boundary under nucleus---a mismatch that creates reversal risk in cross-strategy transfer (\S\ref{sec:generalization}).
130	
131	\paragraph{Three-tier strategy taxonomy.}
132	The trajectory data suggests a functional classification.
133	Nucleus sampling ($p{=}0.95$) serves as a stable baseline with moderate signal strength.
134	Temperature sampling ($\tau{=}0.9$) enhances the signal via accelerated convergence, yielding higher within-strategy accuracy but strategy-specific depth boundaries.
135	Top-$k$ sampling ($k{=}50$) attenuates the signal---accuracy drops 6--9 points relative to nucleus---because hard truncation at a fixed vocabulary size preserves more of the original distribution's shape across depths, compressing inter-depth distances.
136	Notably, top-$k$ preserves the \emph{direction} of all feature trends despite the magnitude reduction, which has implications for ordinal classifiers that rely on monotonicity (\S\ref{sec:generalization}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "883d1eef-3c3f-4a26-a23f-518f56f5fe36",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "0c127cc4-eb83-444f-ad2e-4302f4fbd1d4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "content": "\\section{The Depth Degradation Atlas}\n\\label{sec:atlas}\n\nWe systematically characterize how recursive generation reshapes the statistical profile of text across a grid of 3 model families $\\times$ 3 decoding strategies $\\times$ 4 generation depths (d0--d3), yielding 9 experimental configurations each spanning 4 depths.\nFor each cell we train a Random Forest (RF) classifier on the 19 statistical features defined in \\S\\ref{sec:method} and examine (i)~in-distribution depth classification accuracy, (ii)~which features carry depth signal, (iii)~how far into the recursion chain depth remains discriminable, and (iv)~how decoding strategy modulates the degradation trajectory.\n\n\\subsection{In-Distribution Performance}\n\\label{sec:atlas:indist}\n\nTable~\\ref{tab:main_matrix} reports 4-class depth estimation accuracy under 5-fold cross-validation.\nAll 9 cells exceed chance (25\\%) by a wide margin, with accuracy ranging from 69.6\\% to 85.4\\%.\nBoth model family and decoding strategy influence accuracy, with model ordering GPT-2~XL $>$ OLMo $>$ Pythia holding across all strategies.\nTop-$k$ ($k{=}50$) trails by 6--9 percentage points, while temperature and nucleus sampling alternate for the lead depending on model family.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{In-distribution 4-class depth estimation accuracy (\\%) across 3 model families $\\times$ 3 decoding strategies. RF classifier with 19 statistical features, 5-fold CV (std 0.2--0.9pp across all cells). Chance = 25\\%.}\n\\label{tab:main_matrix}\n\\begin{tabular}{lccc}\n\\toprule\nModel & Nucleus & Temp & Top-$k$ \\\\\n & $p{=}0.95$ & $\\tau{=}0.9$ & $k{=}50$ \\\\\n\\midrule\nPythia-1.4B & 78.2 & 76.3 & 69.6 \\\\\nOLMo-1B & 78.8 & 82.0 & 74.2 \\\\\nGPT-2 XL & 83.3 & \\textbf{85.4} & 76.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nBecause the human-written seed text (d0) is often trivially separable from any machine-generated depth, we also evaluate 3-class accuracy excluding d0.\nPerformance drops moderately---GPT-2~XL with temperature sampling still reaches 82.0\\%, and even the weakest setting (Pythia nucleus) retains 70.8\\%---confirming that the classifier captures inter-generation differences beyond the human--machine boundary.\n\n\\subsection{Feature Universality}\n\\label{sec:atlas:features}\n\nTo identify which statistical fingerprints carry depth signal, we train a dedicated binary RF per cell (d$_i$ vs.\\ rest) and extract feature importances (Gini impurity; permutation importance yields consistent rankings, Appendix~\\ref{app:permutation}).\nFigure~\\ref{fig:atlas_heatmap} visualizes the top-7 feature importances across all 9 cells.\n\nTwo features dominate.\nThe 90th-percentile perplexity (\\textsc{p90\\_ppl}) ranks in the top 2 in all 9 cells, while surprisal variance (\\textsc{var\\_surprisal}) does so in 7 of 9.\nIn the two exceptions---GPT-2~XL with temperature and top-$k$ sampling---the 75th-percentile perplexity (\\textsc{p75\\_ppl}) replaces surprisal variance in the top 2, though surprisal variance remains among the top 4 features.\nTo quantify cross-model agreement, we compute the Spearman rank correlation of the full 19-feature importance vectors across all $\\binom{9}{2}=36$ cell pairs and obtain a mean $\\rho = 0.868$ (range: 0.619--0.954).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_atlas_heatmap.pdf}\n\\caption{Feature importance heatmap across 9 cells (3 models $\\times$ 3 strategies). Top-7 features by mean importance. \\textsc{p90\\_ppl} appears in the top 2 for all cells; \\textsc{var\\_surprisal} for 7 of 9.}\n\\label{fig:atlas_heatmap}\n\\end{figure}\n\nThese results align with theoretical predictions: recursive finetuning erodes the tail of the token-probability distribution \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails}, and high-percentile perplexity directly measures tail behavior.\nThe universality of these markers across architectures and decoding strategies suggests they reflect a structural property of the recursive generation process rather than model-specific artifacts.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:atlas:edd}\n\nAggregate accuracy masks that adjacent depths become harder to distinguish as depth increases; we quantify this via the \\emph{Effective Discriminable Depth} (EDD).\nFor each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary RF (500 trees, 5-fold stratified CV) and compute $\\mathrm{AUC}(d, d{+}1)$ (Eq.~\\ref{eq:edd}).\nWe set $T{=}0.75$ as the default threshold---the midpoint between chance AUC (0.5) and perfect discrimination (1.0)---and report sensitivity at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ below.\n\nWithin the 4-class atlas (d0--d3), 7 of 9 cells achieve $\\mathrm{EDD}_{0.75}=3$; the two exceptions are Pythia and OLMo with top-$k$ sampling ($\\mathrm{EDD}_{0.75}=2$), consistent with top-$k$'s signal-attenuating effect noted in \\S\\ref{sec:atlas:indist}.\n\nWe extend the Pythia-1.4B nucleus pipeline to 6 depths (d0--d5) and train a 500-tree binary RF for each adjacent pair.\nFigure~\\ref{fig:auc_decay} shows the pairwise AUC decay curve.\nThe d0\\,vs.\\,d1 boundary is near-perfect (AUC\\,=\\,0.998), reflecting the well-known human--machine gap.\nSubsequent boundaries degrade monotonically: d1\\,vs.\\,d2 achieves 0.925 [95\\% CI: 0.914,\\,0.935], d2\\,vs.\\,d3 reaches 0.823 [0.805,\\,0.840], and d3\\,vs.\\,d4 yields 0.784 [0.765,\\,0.802]---with the confidence interval lower bound still exceeding $T{=}0.75$.\nAt d4\\,vs.\\,d5, AUC drops to 0.683 [0.661,\\,0.705], falling below the threshold and fixing $\\mathrm{EDD}_{0.75}=4$.\n\n\\paragraph{Cross-model EDD.}\nWe extend the same d0--d5 pipeline to OLMo-1B and GPT-2~XL (both nucleus $p{=}0.95$).\nThe d3\\,vs.\\,d4 AUC consistently clusters near the 0.75 threshold: Pythia 0.784 ($p{=}0.001$), OLMo 0.765 ($p{=}0.091$, marginal), GPT-2~XL 0.750 ($p{=}0.505$, n.s.)---only Pythia achieves conventional significance, yet all three exhibit the same directional pattern.\nAt d4\\,vs.\\,d5, AUC uniformly drops below 0.70 (Pythia 0.683, OLMo 0.684, GPT-2~XL 0.681), fixing $\\mathrm{EDD}_{0.75}{=}4$ for all three models.\nThis cross-model EDD is stable across threshold choices: all three yield $\\mathrm{EDD}{=}5$ at $T{=}0.65$, $\\mathrm{EDD}{=}4$ at $T \\in \\{0.70, 0.75\\}$, and $\\mathrm{EDD}{=}3$ at $T{=}0.80$, matching the single-model pattern in Table~\\ref{tab:edd_sensitivity}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_auc_decay.pdf}\n\\caption{Binary pairwise AUC between adjacent depths (Pythia-1.4B, nucleus $p{=}0.95$, d0--d5). Shaded bands: 95\\% bootstrap CI. Dashed line: $T{=}0.75$. $\\mathrm{EDD}_{0.75}=4$: depth pairs up to d3\\,vs.\\,d4 remain discriminable.}\n\\label{fig:auc_decay}\n\\end{figure}\n\nTable~\\ref{tab:edd_sensitivity} shows the sensitivity of EDD to the choice of threshold.\nAt $T{=}0.65$, all pairs through d4\\,vs.\\,d5 pass, giving $\\mathrm{EDD}=5$.\nAt $T{=}0.80$, only d1\\,vs.\\,d2 and d2\\,vs.\\,d3 pass, yielding $\\mathrm{EDD}=3$.\nThe d0\\,vs.\\,d1 pair passes at every threshold ($\\text{AUC}\\geq0.99$).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{EDD sensitivity to threshold $T$ (Pythia-1.4B, nucleus $p{=}0.95$). \\checkmark: pairwise AUC $\\geq T$; ---: below $T$. d0\\,vs.\\,d1 always passes (AUC$\\geq$0.99) and is omitted.}\n\\label{tab:edd_sensitivity}\n\\begin{tabular}{cccccr}\n\\toprule\n$T$ & d1/d2 & d2/d3 & d3/d4 & d4/d5 & EDD \\\\\n\\midrule\n0.65 & \\checkmark & \\checkmark & \\checkmark & \\checkmark & 5 \\\\\n0.70 & \\checkmark & \\checkmark & \\checkmark & --- & 4 \\\\\n0.75 & \\checkmark & \\checkmark & \\checkmark & --- & 4 \\\\\n0.80 & \\checkmark & \\checkmark & --- & --- & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Granularity ablation.}\nDecision boundary dilution motivates EDD's binary-pair design: mean accuracy drops from 99.5\\% (binary) to 78.3\\% (4-class) to 62.9\\% (6-class), and the d2\\,vs.\\,d3 AUC falls from 0.804 to 0.689 between the 4-class and 6-class settings for Pythia nucleus---a 14\\% relative decline attributable to boundary dilution, not signal loss.\n\n\\subsection{Strategy-Dependent Trajectories}\n\\label{sec:atlas:trajectories}\n\nThe atlas reveals that decoding strategy does not merely scale the overall signal strength---it reshapes the degradation trajectory.\nFigure~\\ref{fig:feature_trajectory} plots normalized feature means across depths for three key features.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_feature_trajectory.pdf}\n\\caption{Normalized feature trajectories across generation depths for 3 models $\\times$ 2 strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$). All features decrease monotonically with depth, but inter-depth spacing is highly non-uniform. Top-$k$ results are provided in Appendix~\\ref{app:topk_trajectories}.}\n\\label{fig:feature_trajectory}\n\\end{figure}\n\n\\paragraph{Non-uniform inter-depth spacing.}\nFor Pythia nucleus, \\textsc{p90\\_ppl} drops from 483.7 (d0) to 61.4 (d1)---an 87\\% reduction---but only from 29.7 (d2) to 18.2 (d3), a 39\\% reduction.\nThis geometric compression of the feature space explains why adjacent-pair AUC decays monotonically (Figure~\\ref{fig:auc_decay}): each successive generation step yields diminishing statistical displacement.\n\n\\paragraph{Temperature-induced acceleration.}\nTemperature sampling ($\\tau{=}0.9$) applies uniform logit scaling rather than the hard truncation of nucleus or top-$k$, which accelerates convergence toward the low-entropy attractor described by \\citet{marchi2024_heat_death}.\nConcretely, feature values at depth $N$ under temperature sampling approximate those at depth $N{+}1$ under nucleus or top-$k$.\nThis shift yields higher in-distribution accuracy (Table~\\ref{tab:main_matrix}) because each depth occupies a more distinct region of feature space, but it also means the d1/d2 boundary under temperature is closer to the d2/d3 boundary under nucleus---a mismatch that creates reversal risk in cross-strategy transfer (\\S\\ref{sec:generalization}).\n\n\\paragraph{Three-tier strategy taxonomy.}\nThe trajectory data suggests a functional classification.\nNucleus sampling ($p{=}0.95$) serves as a stable baseline with moderate signal strength.\nTemperature sampling ($\\tau{=}0.9$) enhances the signal via accelerated convergence, yielding higher within-strategy accuracy but strategy-specific depth boundaries.\nTop-$k$ sampling ($k{=}50$) attenuates the signal---accuracy drops 6--9 points relative to nucleus---because hard truncation at a fixed vocabulary size preserves more of the original distribution's shape across depths, compressing inter-depth distances.\nNotably, top-$k$ preserves the \\emph{direction} of all feature trends despite the magnitude reduction, which has implications for ordinal classifiers that rely on monotonicity (\\S\\ref{sec:generalization}).",
      "numLines": 136,
      "startLine": 1,
      "totalLines": 136
    }
  },
  "sourceToolAssistantUUID": "883d1eef-3c3f-4a26-a23f-518f56f5fe36",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-15T15:20:55.324Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GjgKJxwbc2Fx7xuSBmE6Ys`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0c127cc4-eb83-444f-ad2e-4302f4fbd1d4",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "292e16e0-1359-4261-a2b9-593e0e87d2cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-15T15:20:55.333Z_

<details><summary>↩ Tool result · `toolu_01GjgKJxwbc2Fx7xuSBmE6Ys`</summary>

```text
1	\section{Introduction}
2	\label{sec:intro}
3	
4	The text on which large language models are trained increasingly contains their own outputs.
5	As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
6	This model$\to$data$\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
7	
8	Existing tools address adjacent but distinct problems.
9	Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
10	Watermarking \cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.
11	The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
12	No existing method estimates the ordinal recursive depth of a text passage from its content alone.
13	
14	Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints exhibit universal stability across model families and decoding strategies.
15	Specifically, perplexity tail statistics---the 90th-percentile perplexity (\textsc{p90\_ppl}) and surprisal variance (\textsc{var\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 7/9 model--strategy configurations, respectively.
16	
17	We formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.
18	Given a text passage, we compute a 19-dimensional feature vector from reference-model perplexity statistics---capturing distributional location, spread, tail behavior, and lexical diversity---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).
19	To systematically characterize how recursive generation reshapes these features, we construct the \emph{Depth Degradation Atlas}: a $3 \times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.
20	The atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.
21	
22	Our contributions are:
23	
24	\begin{itemize}
25	    \item \textbf{Task formalization.} We define recursive generation depth estimation as ordinal classification and introduce the EDD metric, which summarizes the maximum depth at which adjacent generations remain separable above a given AUC threshold.
26	
27	    \item \textbf{Depth Degradation Atlas.} We construct a systematic $3 \times 3$ map across model families and decoding strategies, revealing that \textsc{p90\_ppl} ranks in the top 2 in all 9 cells (100\%) and \textsc{var\_surprisal} in 7/9 (78\%), with a mean Spearman rank correlation of $\rho{=}0.868$ across importance vectors. The extended Pythia nucleus pipeline (d0--d5) yields $\mathrm{EDD}_{0.75}{=}4$, establishing that depth discrimination persists through four recursive steps before falling below threshold.
28	
29	    \item \textbf{Generalization analysis.} Cross-model leave-one-out transfer achieves 66.4\% and cross-strategy transfer 59.1\% (chance = 25\%). We identify a temperature-induced d1/d2 AUC inversion (GPT-2~XL: 0.129, OLMo: 0.253) that z-score normalization cannot resolve, confirming a geometry-level shift.
30	
31	    \item \textbf{End-to-end learning as negative result.} Both DeBERTa-v3-base (58.3\%) and RoBERTa-base (59.5\%) achieve ${\sim}$59\% via end-to-end finetuning---19pp below feature-based classifiers (78.2\%)---with the architecture-invariant gap ruling out model selection bias. Probing reveals significant negative correlations (DeBERTa: $\rho{=}{-}0.48$, RoBERTa: $\rho{=}{-}0.46$) between transformer attention and RF feature importance, confirming complementary representations.
32	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "292e16e0-1359-4261-a2b9-593e0e87d2cc",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "016d494f-c6c4-40ad-b265-ce9279855d87",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive depth of a text passage from its content alone.\n\nOur key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints exhibit universal stability across model families and decoding strategies.\nSpecifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 7/9 model--strategy configurations, respectively.\n\nWe formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.\nGiven a text passage, we compute a 19-dimensional feature vector from reference-model perplexity statistics---capturing distributional location, spread, tail behavior, and lexical diversity---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).\nTo systematically characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.\nThe atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\n\\begin{itemize}\n    \\item \\textbf{Task formalization.} We define recursive generation depth estimation as ordinal classification and introduce the EDD metric, which summarizes the maximum depth at which adjacent generations remain separable above a given AUC threshold.\n\n    \\item \\textbf{Depth Degradation Atlas.} We construct a systematic $3 \\times 3$ map across model families and decoding strategies, revealing that \\textsc{p90\\_ppl} ranks in the top 2 in all 9 cells (100\\%) and \\textsc{var\\_surprisal} in 7/9 (78\\%), with a mean Spearman rank correlation of $\\rho{=}0.868$ across importance vectors. The extended Pythia nucleus pipeline (d0--d5) yields $\\mathrm{EDD}_{0.75}{=}4$, establishing that depth discrimination persists through four recursive steps before falling below threshold.\n\n    \\item \\textbf{Generalization analysis.} Cross-model leave-one-out transfer achieves 66.4\\% and cross-strategy transfer 59.1\\% (chance = 25\\%). We identify a temperature-induced d1/d2 AUC inversion (GPT-2~XL: 0.129, OLMo: 0.253) that z-score normalization cannot resolve, confirming a geometry-level shift.\n\n    \\item \\textbf{End-to-end learning as negative result.} Both DeBERTa-v3-base (58.3\\%) and RoBERTa-base (59.5\\%) achieve ${\\sim}$59\\% via end-to-end finetuning---19pp below feature-based classifiers (78.2\\%)---with the architecture-invariant gap ruling out model selection bias. Probing reveals significant negative correlations (DeBERTa: $\\rho{=}{-}0.48$, RoBERTa: $\\rho{=}{-}0.46$) between transformer attention and RF feature importance, confirming complementary representations.\n\\end{itemize}",
      "numLines": 32,
      "startLine": 1,
      "totalLines": 32
    }
  },
  "sourceToolAssistantUUID": "292e16e0-1359-4261-a2b9-593e0e87d2cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-15T15:20:55.774Z_

<details open><summary>🔧 Tool call — Read · `toolu_018ffwjSv7sx9j5RpE1ftt4X`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/writing_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "016d494f-c6c4-40ad-b265-ce9279855d87",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "5c3ae3f9-178d-48c5-a7aa-eaf81ff4f06e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-15T15:20:55.781Z_

<details><summary>↩ Tool result · `toolu_018ffwjSv7sx9j5RpE1ftt4X`</summary>

```text
1	# Writing Plan — recursive_gen_depth_est
2	# Generated: 2026-05-15 by Paper Agent
3	# Contract for all downstream Workers — Director 审批后生效
4	
5	meta:
6	  venue: EMNLP 2026
7	  track: "ARR May 2026 — New Missions for NLP Research"
8	  template: "acl2023"
9	  template_note: "需下载 ARR/ACL 官方 LaTeX 模板到 templates/latex/emnlp2026/；当前使用 acl2023 style 规范"
10	  page_limit: 8
11	  deadline: "2026-05-25"
12	  title: "How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints"
13	  core_claim: >
14	    Recursive generation leaves quantifiable statistical fingerprints —
15	    perplexity tail statistics (p90_ppl, var_surprisal) universally mark
16	    generation depth across 3 model families × 3 decoding strategies,
17	    enabling 70–85% four-class depth estimation (chance=25%). The Depth
18	    Degradation Atlas reveals that decoding strategy fundamentally shapes
19	    degradation trajectories rather than merely attenuating them.
20	  contributions:
21	    - "C1: Task formalization — define recursive generation depth estimation + EDD metric"
22	    - "C2: Depth Degradation Atlas — 3×3 systematic map with p90_ppl/var_surprisal universality, strategy-dependent trajectories, EDD=4"
23	    - "C3: Cross-model (66.4%) and cross-strategy (59.1%) generalization analysis, including temp09 d1v2 reversal mechanism + z-score mitigation"
24	    - "C4: DCOL 6× failure as negative result — end-to-end contrastive ordinal learning insufficient vs statistical features + simple classifiers"
25	  flags: []
26	  created_at: "2026-05-15T12:00:00Z"
27	
28	# ============================================================
29	# PAPER OUTLINE
30	# ============================================================
31	paper_outline:
32	
33	  - section: abstract
34	    word_budget: 150
35	    core_bullets:
36	      - "问题: Web 语料中多代递归合成文本深度不可知，binary detectors 丢弃 ordinal 信息"
37	      - "方法: 定义 recursive generation depth estimation，构建 3M×3S×4D benchmark，19-dim 统计特征 + RF"
38	      - "结果: 70–85% 4-class acc (chance=25%), p90_ppl/var_surprisal 100%/78% top-2, EDD=4 (binary pairwise), cross-model 66.4%"
39	      - "发现: 解码策略根本性塑造 degradation trajectory — temp d1/d2 boundary 反转 (AUC 0.13), z-score 部分恢复"
40	    dependencies: [atlas, generalization, method]
41	    tables: []
42	    figures: []
43	    registry_refs: []
44	
45	  - section: introduction
46	    word_budget: 900
47	    core_bullets:
48	      - "Hook: LLM 语料中合成文本比例快速增长，model→data→model 递归循环已在 wild 中发生，但我们无法判断文本经历了多少轮递归——这一区分对 data curation 至关重要（1st-gen 可能有益，deeply recursive 驱动 collapse）"
49	      - "Gap: Binary detectors (Binoculars, Fast-DetectGPT, DivEye) 仅区分 real/synthetic; model collapse 研究 (Shumailov Nature, Dohmatob ICML) 假设深度已知; EditLens 估计单次编辑程度但不涉及递归深度——没有方法从文本本身估计 ordinal recursive depth"
50	      - "Insight: 递归生成在文本中留下可量化统计指纹，特别是 perplexity tail statistics (p90_ppl, var_surprisal)，跨 3 个模型族 × 3 种解码策略具有 universal stability"
51	      - "Mechanism: 19-dim reference-model perplexity features + RF → ordinal depth estimation; Depth Degradation Atlas 系统性刻画 feature-depth 演变"
52	      - "Contributions: C1-C4 (task formalization + EDD, Atlas, generalization analysis, DCOL negative result)"
53	    dependencies: [atlas, generalization]
54	    citation_hints:
55	      - "shumailov2024_nature, alemohammad2024_mad: model collapse 基础"
56	      - "editlens2026: 最近邻 (editing extent vs recursive depth)"
57	      - "binoculars2024, fast_detectgpt2024, diveye2026: binary detectors"
58	      - "drayson2025: detection prevents collapse"
59	    figures: []
60	    tables: []
61	    registry_refs: []
62	
63	  - section: related_work
64	    word_budget: 600
65	    core_bullets:
66	      - "Model Collapse Theory: Shumailov(Nature) tail erosion, Dohmatob(tale of tails) tail narrowing vs cutting, Alemohammad(MAD) precision-recall tradeoff, Gerstgrasser(accumulation) mitigation, Drayson(EMNLP2025) detection+collapse — 刻画 degradation patterns 但假设深度已知 a priori"
67	      - "AI Text Detection: DetectGPT(curvature), Binoculars(ppl ratio), Fast-DetectGPT, DivEye(surprisal diversity), GLTR(statistical) — binary classification, 丢弃 ordinal depth"
68	      - "Adjacent Tasks: EditLens(editing extent, continuous), Uchendu(multi-source attribution) — 相邻维度但不估计 recursive depth"
69	      - "Decoding Strategy Effects: Holtzman(nucleus), Finlayson(closing), Garces Arias(COLING2025 model-dependent) — 我们揭示策略对 depth signal 的差异化影响，超越单纯 text quality 层面"
70	    dependencies: [introduction]
71	    citation_hints:
72	      - "kirchenbauer2023_watermark: proactive vs post-hoc"
73	      - "sadasivan2023_paraphrase: detection limits"
74	      - "coral2020, cloc2025: ordinal classification methods"
75	    figures: []
76	    tables: []
77	    registry_refs: []
78	
79	  - section: method
80	    title: "Task Formulation"
81	    subsections:
82	      - "3.1 Problem Definition"
83	      - "3.2 Multi-Generational Benchmark"
84	      - "3.3 Statistical Feature Design"
85	      - "3.4 Effective Discriminable Depth (EDD)"
86	    word_budget: 1000
87	    core_bullets:
88	      - "Definition: Given text x, estimate recursive generation depth d ∈ {0,1,...,K}, where d=0 = human-written"
89	      - "Benchmark: 3 models (Pythia-1.4B, OLMo-1B, GPT-2 XL) × 3 strategies (nucleus p=0.95, temp τ=0.9, top-k k=50) × 4 depths (d0-d3), 5000 samples/cell, total 180k samples"
90	      - "Pipeline: seed text (OpenWebText/Dolma/WebText) → LoRA finetune → generate → repeat; reference model GPT-2 base (独立于生成模型)"
91	      - "Features: 19-dim — perplexity statistics (mean/var/skewness/kurtosis/p10/p25/p50/p75/p90 PPL, 9 features), surprisal statistics (mean/var surprisal + entropy_of_surprisal, 3 features), lexical diversity (TTR, hapax ratio, bigram_entropy, trigram_entropy, 4 features), repetition (rep_2gram/rep_3gram/rep_4gram fractions, 3 features)"
92	      - "EDD: EDD_T = max d* s.t. AUC(d*, d*+1) ≥ T, default T=0.75; report sensitivity at T ∈ {0.65, 0.70, 0.75, 0.80}"
93	      - "Classifiers: RF(200 trees) primary, CORAL/DivEye/CE-MLP/LR as baselines; single-feature ppl regression as lower bound"
94	      - "Reference model specification: GPT-2 base (124M), cross-model LOO 时不换 ref model, circularity discussion in §6"
95	    dependencies: []
96	    notation_table:
97	      d: "recursive generation depth (d=0 human)"
98	      K: "maximum depth in benchmark"
99	      EDD_T: "Effective Discriminable Depth at AUC threshold T"
100	      f_x: "19-dim statistical feature vector"
101	      M: "{Pythia-1.4B, OLMo-1B, GPT-2 XL}"
102	      S: "{nucleus p=0.95, temp τ=0.9, top-k k=50}"
103	    figures: []
104	    tables: [tab_features]
105	    registry_refs: [mvp_pipeline_pythia_002]
106	
107	  - section: atlas
108	    title: "The Depth Degradation Atlas"
109	    subsections:
110	      - "4.1 In-Distribution Performance"
111	      - "4.2 Feature Universality"
112	      - "4.3 Monotonicity and Inter-Depth Distances"
113	      - "4.4 EDD Analysis"
114	      - "4.5 Strategy-Dependent Trajectories"
115	    word_budget: 1200
116	    core_bullets:
117	      - "3×3 matrix: 70–85% RF 4-class acc; GPT-2 XL temp09 best (85.4%), Pythia topk50 lowest (69.6%); model and strategy effects are comparable in magnitude (strategy slightly larger: 8.4pp vs 7.1pp)"
118	      - "Feature universality: p90_ppl top-2 in 9/9 cells (100%), var_surprisal top-2 in 7/9 (78%); cross-model rank correlation mean=0.868 [0.619–0.954]"
119	      - "Monotonicity: ρ = -0.82 to -0.89; non-uniform inter-depth distances (d0→d1 gap >> d2→d3 gap); feature importance evolves — var_surprisal dominant at shallow, p90_ppl/kurtosis at deep"
120	      - "EDD: 7/9 cells EDD≥3 at T=0.75; binary pairwise verification EDD=4 (Pythia nucleus: d3v4 AUC=0.784 > 0.75, d4v5 AUC=0.683 < 0.75)"
121	      - "EDD sensitivity: report at T ∈ {0.65, 0.70, 0.75, 0.80}"
122	      - "Three-tier strategy classification: nucleus=baseline stable, temperature=signal enhancement BUT d1v2 boundary reversal risk, top-k=signal attenuation but direction preserved"
123	      - "Temperature reversal mechanism: uniform logit scaling (vs truncation) accelerates convergence to attractor distribution — temp09 depth N features ≈ nucleus/topk50 depth N+1; GPT-2 XL temp09 d1 p90_ppl median=92.2 falls into nucleus/topk50 d2 range 65–92"
124	    dependencies: []
125	    tables: [tab_main_matrix, tab_feature_importance]
126	    figures: [fig_auc_decay, fig_feature_trajectory, fig_atlas_heatmap]
127	    registry_refs:
128	      - mvp_pipeline_pythia_002
129	      - pythia_temp09_001
130	      - pythia_topk50_001
131	      - cross_model_olmo_002
132	      - olmo_temp09_001
133	      - olmo_topk50_001
134	      - cross_model_gpt2xl_001
135	      - gpt2xl_temp09_001
136	      - gpt2xl_topk50_001
137	      - atlas_v2_analysis
138	      - depth_extension_binary_pairwise_002
139	      - depth_extension_pythia_d4d5_001
140	
141	  - section: generalization
142	    title: "Generalization and Robustness"
143	    subsections:
144	      - "5.1 Baseline Comparison"
145	      - "5.2 Cross-Model Transfer"
146	      - "5.3 Cross-Strategy Transfer"
147	      - "5.4 End-to-End Learning: A Negative Result"
148	    word_budget: 1000
149	    core_bullets:
150	      - "Baselines (Pythia nucleus): RF 78.2% ≈ CORAL 78.1% ≈ DivEye 78.2% > CE-MLP 74.9% > LR 75.0% > DeepSeek V3.2 zero-shot 40.0% (200 samples, Pythia nucleus only) >> ppl-regression 25.1% (chance); feature-based methods outperform both LLM zero-shot and single-feature"
151	      - "Cross-model LOO: mean 66.4% (gate 45% ✓); Pythia 62.4%, OLMo 69.2%, GPT-2 XL 67.6%; depth_0 recall >98% inflates headline — per-class: d2 recall as low as 26.8% (Pythia holdout)"
152	      - "Cross-strategy LOO: mean 59.1%; nucleus holdout best (65.4–69.4%), topk50 holdout worst (51.5–54.9%); temp09 holdout d1v2 AUC inverts (GPT-2 XL 0.13, OLMo 0.25)"
153	      - "Z-score normalization: two-layer structure — LR nucleus/topk holdout d1v2 AUC 0.61–0.89 (scale shift, normalization-fixable), BUT temp09 holdout d1v2 AUC remains <0.5 (GPT-2 XL 0.24); RF unchanged (Δ<0.02pp, tree-invariant). Temperature decoding induces qualitatively different feature distributions beyond linear rescaling"
154	      - "DCOL v1-v6: 6 attempts all failed; v6 RoBERTa-large best 64.5% (vs RF 78.2%), severe overfitting (train 75% vs val 64.4% at epoch 1); embedding collapse (v1-v3), OOM (v4), NaN (v5) → end-to-end contrastive ordinal learning insufficient for text depth"
155	    dependencies: []
156	    tables: [tab_baselines, tab_cross_model, tab_cross_strategy]
157	    figures: [fig_confusion_matrix]
158	    registry_refs:
159	      - baseline_battery_001
160	      - baseline_battery_9cell_001
161	      - cross_model_loo_v1
162	      - cross_strategy_loo_001
163	      - cross_strategy_loo_zscore_001
164	      - dcol_roberta_v6_001
165	
166	  - section: discussion
167	    title: "Discussion and Limitations"
168	    subsections:
169	      - "6.1 Implications"
170	      - "6.2 Limitations"
171	    word_budget: 500
172	    core_bullets:
173	      - "Depth-graduated curation: predicted depth as finer-grained quality proxy than binary labels (conceptual, empirical validation deferred)"
174	      - "Feature evolution: var_surprisal→p90_ppl/kurtosis shift from shallow to deep consistent with Shumailov tail erosion theory"
175	      - "Cross-strategy deployment: 需先验知道目标策略类型, 否则 d1/d2 预测可能反转"
176	      - "Controlled setting: 固定 seed text + LoRA finetuning + 3 models at 1-1.5B scale; wild-data transfer + 7B+ scale 待验证"
177	      - "Reference model circularity: GPT-2 base 作为 ref model, cross-model LOO 时 GPT-2 XL holdout 存在 partial overlap — 但 GPT-2 XL holdout 并非最高 (67.6% < OLMo 69.2%)"
178	      - "Feature domain fragility: Pudasaini et al. 发现 detection features 在 domain shift 下退化, ordinal depth features 可能同样脆弱"
179	    dependencies: [atlas, generalization]
180	    citation_hints:
181	      - "bakshi2026: non-monotonic dynamics complicating depth assumption"
182	      - "dsir2023, qurating2024: data curation context"
183	      - "marchi2024: temperature convergence theory support"
184	      - "pudasaini2026: feature fragility under distribution shift"
185	      - "falahati2026: curated pipelines harder case"
186	      - "sugiyama2007: covariate shift theory"
187	    figures: []
188	    tables: []
189	    registry_refs: []
190	
191	  - section: conclusion
192	    word_budget: 200
193	    core_bullets:
194	      - "Summary: 定义 recursive depth estimation 任务, 构建 Depth Degradation Atlas, 揭示 universal (p90_ppl/var_surprisal) + strategy-dependent (temperature reversal) 双层信号结构"
195	      - "Key numbers: 70–85% in-distribution, EDD=4, cross-model 66.4%, cross-strategy 59.1%"
196	      - "Future: wild-data calibration, 7B+ scale, strategy-conditioned classifiers, depth-graduated curation experiments"
197	    dependencies: [atlas, generalization, discussion]
198	    figures: []
199	    tables: []
200	    registry_refs: []
201	
202	# ============================================================
203	# VISUALIZATION PLAN (≥4 figures, Dream D002 requirement)
204	# ============================================================
205	visualization_plan:
206	
207	  - fig_id: fig_auc_decay
208	    type: statistical
209	    tool: matplotlib
210	    description: "Pairwise AUC decay curve across adjacent depth pairs (d0v1 → d4v5) with horizontal EDD threshold lines at T=0.65/0.70/0.75/0.80. Show binary pairwise AUC (solid) vs 4-class pipeline AUC (dashed) for Pythia nucleus. Mark EDD=4 crossing point."
211	    data_source: "registry: depth_extension_binary_pairwise_002, mvp_pipeline_pythia_002, depth_extension_pythia_d4d5_001"
212	    placement: atlas
213	    aspect_ratio: "4:3"
214	    notes: "X-axis: depth pair (d0v1, d1v2, d2v3, d3v4, d4v5); Y-axis: AUC; horizontal lines at T thresholds"
215	
216	  - fig_id: fig_feature_trajectory
217	    type: statistical
218	    tool: matplotlib
219	    description: "Feature trajectory panel: top-5 features (p90_ppl, var_surprisal, mean_ppl, mean_surprisal, p75_ppl) median values across depth 0-3, one subplot per model family (3 subplots). Each subplot shows 3 strategies as different line styles. Highlights non-uniform inter-depth distances and temperature reversal."
220	    data_source: "registry: atlas_v2_analysis; raw feature data from 9 cell experiments"
221	    placement: atlas
222	    aspect_ratio: "16:5"
223	    notes: "3-panel figure (Pythia | OLMo | GPT-2 XL). Shared legend. Log-scale y-axis for PPL features."
224	
225	  - fig_id: fig_atlas_heatmap
226	    type: statistical
227	    tool: matplotlib
228	    description: "Atlas feature importance heatmap: 9-cell grid (3 models × 3 strategies) showing top-5 feature importance values. Color = importance magnitude, cell annotation = rank. Highlights p90_ppl/var_surprisal universality."
229	    data_source: "registry: atlas_v2_analysis, baseline_battery_9cell_001"
230	    placement: atlas
231	    aspect_ratio: "4:3"
232	    notes: "Rows = features (top-5), Columns = 9 cells grouped by model. Okabe-Ito colormap."
233	
234	  - fig_id: fig_confusion_matrix
235	    type: statistical
236	    tool: matplotlib
237	    description: "Confusion matrix heatmap for best in-distribution setting (GPT-2 XL temp09, 85.4%) and best cross-model LOO setting (OLMo holdout, 69.2%). Two-panel figure showing in-distribution vs transfer performance."
238	    data_source: "registry: gpt2xl_temp09_001, cross_model_loo_v1"
239	    placement: generalization
240	    aspect_ratio: "8:3"
241	    notes: "2-panel. Normalized by true class. Annotate counts + percentages."
242	
243	# ============================================================
244	# TABLE PLAN
245	# ============================================================
246	table_plan:
247	
248	  - table_id: tab_main_matrix
249	    caption: "In-distribution 4-class depth estimation accuracy (\\%) across 3 model families × 3 decoding strategies. RF classifier, 19 statistical features."
250	    placement: atlas
251	    type: comparison
252	    columns: [Model, "nucleus p=0.95", "temp τ=0.9", "top-k k=50"]
253	    data_source: "registry: mvp_pipeline_pythia_002, pythia_temp09_001, pythia_topk50_001, cross_model_olmo_002, olmo_temp09_001, olmo_topk50_001, cross_model_gpt2xl_001, gpt2xl_temp09_001, gpt2xl_topk50_001"
254	    notes: "Bold best per row. Also include 3-class (d1-d3 only) acc as companion metric (Dream D002 req #5)."
255	
256	  - table_id: tab_features
257	    caption: "19 statistical features extracted from reference-model perplexity distributions."
258	    placement: method
259	    type: configuration
260	    columns: [Feature, Description, Category]
261	    data_source: "manual"
262	    notes: "Grouped by category: perplexity stats, surprisal stats, lexical diversity, burstiness. 可移至 appendix 如空间不足."
263	
264	  - table_id: tab_feature_importance
265	    caption: "Top-5 feature importance ranking across 9 benchmark cells. p90_ppl appears in top-2 for all 9 cells."
266	    placement: atlas
267	    type: statistics
268	    columns: [Cell, "Rank 1", "Rank 2", "Rank 3", "Rank 4", "Rank 5"]
269	    data_source: "registry: atlas_v2_analysis"
270	    notes: "Highlight p90_ppl and var_surprisal entries. 可与 fig_atlas_heatmap 二选一如空间不足."
271	
272	  - table_id: tab_baselines
273	    caption: "Comparison of classification methods on Pythia-1.4B nucleus (baseline setting)."
274	    placement: generalization
275	    type: comparison
276	    columns: [Method, "4-class Acc", "3-class Acc", "d1v2 AUC", "d2v3 AUC"]
277	    data_source: "registry: baseline_battery_001, mvp_pipeline_pythia_002"
278	    notes: "Methods: RF, CORAL, DivEye, CE-MLP, LR, DeepSeek V3.2 (zero-shot, 200 samples), ppl-regression (single feature)."
279	
280	  - table_id: tab_cross_model
281	    caption: "Cross-model leave-one-out generalization. Train on 2 model families, test on held-out 3rd."
282	    placement: generalization
283	    type: comparison
284	    columns: [Holdout, "4-class Acc", "d0 Recall", "d1 Recall", "d2 Recall", "d3 Recall", "d1v2 AUC"]
285	    data_source: "registry: cross_model_loo_v1"
286	    notes: "Report per-class recall to expose d0 inflation. Chance = 25%."
287	
288	  - table_id: tab_cross_strategy
289	    caption: "Cross-strategy leave-one-out transfer. Per-model accuracy when one strategy is held out."
290	    placement: generalization
291	    type: comparison
292	    columns: [Holdout, "Pythia Acc", "OLMo Acc", "GPT-2 XL Acc", "d1v2 AUC (GPT-2 XL)", "d1v2 AUC (OLMo)"]
293	    data_source: "registry: cross_strategy_loo_001, cross_strategy_loo_zscore_001"
294	    notes: "Highlight temp09 d1v2 AUC inversion (0.13/0.25). Add z-score row for comparison."
295	
296	  - table_id: tab_edd_sensitivity
297	    caption: "EDD at different AUC thresholds (Pythia-1.4B nucleus, binary pairwise)."
298	    placement: atlas
299	    type: statistics
300	    columns: [Threshold, "d1v2", "d2v3", "d3v4", "d4v5", EDD]
301	    data_source: "registry: depth_extension_binary_pairwise_002"
302	    notes: "Dream D002 requirement #6. Show AUC values at each pair and resulting EDD."
303	
304	# ============================================================
305	# LITERATURE STRATEGY
306	# ============================================================
307	literature_strategy:
308	  citation_budget: 35
309	  macro_context:
310	    - "model collapse and recursive generation"
311	    - "AI-generated text detection"
312	    - "decoding strategy effects on text properties"
313	    - "ordinal classification methods"
314	    - "data curation for LLM training"
315	  micro_clusters:
316	    - cluster_name: "Model Collapse Theory"
317	      search_queries:
318	        - "model collapse recursive generation 2024 2025 2026"
319	        - "self-consuming generative models iterative training"
320	      must_cite:
321	        - "shumailov2024_nature"
322	        - "alemohammad2024_mad"
323	        - "dohmatob2024_tale_of_tails"
324	      target_count: 10
325	    - cluster_name: "AI Text Detection"
326	      search_queries:
327	        - "machine-generated text detection statistical 2024 2025"
328	        - "zero-shot LLM detection perplexity"
329	      must_cite:
330	        - "binoculars2024"
331	        - "fast_detectgpt2024"
332	        - "diveye2026"
333	        - "gehrmann2019_gltr"
334	      target_count: 8
335	    - cluster_name: "Decoding Strategy Effects"
336	      search_queries:
337	        - "decoding strategy text generation sampling 2024 2025"
338	        - "nucleus sampling temperature top-k effects"
339	      must_cite:
340	        - "holtzman2020_nucleus"
341	        - "garces_arias2025_decoding_decoded"
342	      target_count: 5
343	    - cluster_name: "Ordinal Classification"
344	      search_queries:
345	        - "ordinal classification contrastive learning 2024 2025"
346	        - "CORAL ordinal regression neural networks"
347	      must_cite:
348	        - "coral2020"
349	        - "cloc2025"
350	      target_count: 3
351	    - cluster_name: "Data Curation & Adjacent"
352	      search_queries:
353	        - "data curation quality scoring LLM training 2024 2025"
354	        - "AI text editing extent detection"
355	      must_cite:
356	        - "editlens2026"
357	        - "kirchenbauer2023_watermark"
358	      target_count: 5
359	
360	# ============================================================
361	# WRITING ORDER (strict serial)
362	# ============================================================
363	writing_order:
364	  - atlas           # Section 4 — PRIMARY contribution, data-driven, write first
365	  - generalization   # Section 5 — secondary experiments, depends on atlas narrative
366	  - method           # Section 3 — formalize based on what atlas/experiments need
367	  - introduction     # Section 1 — frame story around established results
368	  - related_work     # Section 2 — position relative to intro framing
369	  - discussion       # Section 6 — synthesize, includes limitations
370	  - abstract         # condense final narrative
371	  - conclusion       # summarize
372	
373	# ============================================================
374	# APPENDIX PLAN
375	# ============================================================
376	appendix:
377	  - "A: Full 19-feature list with mathematical definitions"
378	  - "B: Per-class precision/recall/F1 for all 9 in-distribution cells"
379	  - "C: DCOL training details (hyperparameters, loss curves, failure modes)"
380	  - "D: Confusion matrices for all 9 cells"
381	  - "E: Full feature importance rankings"
382	  - "F: Depth extension 6-class results (d0-d5)"
383	  - "G: Hyperparameter configurations for benchmark construction"
384	
385	# ============================================================
386	# WORD BUDGET SUMMARY
387	# ============================================================
388	# abstract:       150
389	# introduction:   900
390	# related_work:   600
391	# method:        1000
392	# atlas:         1200
393	# generalization: 1000
394	# discussion:     500
395	# conclusion:     200
396	# ─────────────────
397	# Total:         5550 words + 4 figures + 6-7 tables ≈ 8 pages
398	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5c3ae3f9-178d-48c5-a7aa-eaf81ff4f06e",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "f99078e2-8047-4e65-a587-b76919b0af82",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/writing_plan.yaml",
      "content": "# Writing Plan — recursive_gen_depth_est\n# Generated: 2026-05-15 by Paper Agent\n# Contract for all downstream Workers — Director 审批后生效\n\nmeta:\n  venue: EMNLP 2026\n  track: \"ARR May 2026 — New Missions for NLP Research\"\n  template: \"acl2023\"\n  template_note: \"需下载 ARR/ACL 官方 LaTeX 模板到 templates/latex/emnlp2026/；当前使用 acl2023 style 规范\"\n  page_limit: 8\n  deadline: \"2026-05-25\"\n  title: \"How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\"\n  core_claim: >\n    Recursive generation leaves quantifiable statistical fingerprints —\n    perplexity tail statistics (p90_ppl, var_surprisal) universally mark\n    generation depth across 3 model families × 3 decoding strategies,\n    enabling 70–85% four-class depth estimation (chance=25%). The Depth\n    Degradation Atlas reveals that decoding strategy fundamentally shapes\n    degradation trajectories rather than merely attenuating them.\n  contributions:\n    - \"C1: Task formalization — define recursive generation depth estimation + EDD metric\"\n    - \"C2: Depth Degradation Atlas — 3×3 systematic map with p90_ppl/var_surprisal universality, strategy-dependent trajectories, EDD=4\"\n    - \"C3: Cross-model (66.4%) and cross-strategy (59.1%) generalization analysis, including temp09 d1v2 reversal mechanism + z-score mitigation\"\n    - \"C4: DCOL 6× failure as negative result — end-to-end contrastive ordinal learning insufficient vs statistical features + simple classifiers\"\n  flags: []\n  created_at: \"2026-05-15T12:00:00Z\"\n\n# ============================================================\n# PAPER OUTLINE\n# ============================================================\npaper_outline:\n\n  - section: abstract\n    word_budget: 150\n    core_bullets:\n      - \"问题: Web 语料中多代递归合成文本深度不可知，binary detectors 丢弃 ordinal 信息\"\n      - \"方法: 定义 recursive generation depth estimation，构建 3M×3S×4D benchmark，19-dim 统计特征 + RF\"\n      - \"结果: 70–85% 4-class acc (chance=25%), p90_ppl/var_surprisal 100%/78% top-2, EDD=4 (binary pairwise), cross-model 66.4%\"\n      - \"发现: 解码策略根本性塑造 degradation trajectory — temp d1/d2 boundary 反转 (AUC 0.13), z-score 部分恢复\"\n    dependencies: [atlas, generalization, method]\n    tables: []\n    figures: []\n    registry_refs: []\n\n  - section: introduction\n    word_budget: 900\n    core_bullets:\n      - \"Hook: LLM 语料中合成文本比例快速增长，model→data→model 递归循环已在 wild 中发生，但我们无法判断文本经历了多少轮递归——这一区分对 data curation 至关重要（1st-gen 可能有益，deeply recursive 驱动 collapse）\"\n      - \"Gap: Binary detectors (Binoculars, Fast-DetectGPT, DivEye) 仅区分 real/synthetic; model collapse 研究 (Shumailov Nature, Dohmatob ICML) 假设深度已知; EditLens 估计单次编辑程度但不涉及递归深度——没有方法从文本本身估计 ordinal recursive depth\"\n      - \"Insight: 递归生成在文本中留下可量化统计指纹，特别是 perplexity tail statistics (p90_ppl, var_surprisal)，跨 3 个模型族 × 3 种解码策略具有 universal stability\"\n      - \"Mechanism: 19-dim reference-model perplexity features + RF → ordinal depth estimation; Depth Degradation Atlas 系统性刻画 feature-depth 演变\"\n      - \"Contributions: C1-C4 (task formalization + EDD, Atlas, generalization analysis, DCOL negative result)\"\n    dependencies: [atlas, generalization]\n    citation_hints:\n      - \"shumailov2024_nature, alemohammad2024_mad: model collapse 基础\"\n      - \"editlens2026: 最近邻 (editing extent vs recursive depth)\"\n      - \"binoculars2024, fast_detectgpt2024, diveye2026: binary detectors\"\n      - \"drayson2025: detection prevents collapse\"\n    figures: []\n    tables: []\n    registry_refs: []\n\n  - section: related_work\n    word_budget: 600\n    core_bullets:\n      - \"Model Collapse Theory: Shumailov(Nature) tail erosion, Dohmatob(tale of tails) tail narrowing vs cutting, Alemohammad(MAD) precision-recall tradeoff, Gerstgrasser(accumulation) mitigation, Drayson(EMNLP2025) detection+collapse — 刻画 degradation patterns 但假设深度已知 a priori\"\n      - \"AI Text Detection: DetectGPT(curvature), Binoculars(ppl ratio), Fast-DetectGPT, DivEye(surprisal diversity), GLTR(statistical) — binary classification, 丢弃 ordinal depth\"\n      - \"Adjacent Tasks: EditLens(editing extent, continuous), Uchendu(multi-source attribution) — 相邻维度但不估计 recursive depth\"\n      - \"Decoding Strategy Effects: Holtzman(nucleus), Finlayson(closing), Garces Arias(COLING2025 model-dependent) — 我们揭示策略对 depth signal 的差异化影响，超越单纯 text quality 层面\"\n    dependencies: [introduction]\n    citation_hints:\n      - \"kirchenbauer2023_watermark: proactive vs post-hoc\"\n      - \"sadasivan2023_paraphrase: detection limits\"\n      - \"coral2020, cloc2025: ordinal classification methods\"\n    figures: []\n    tables: []\n    registry_refs: []\n\n  - section: method\n    title: \"Task Formulation\"\n    subsections:\n      - \"3.1 Problem Definition\"\n      - \"3.2 Multi-Generational Benchmark\"\n      - \"3.3 Statistical Feature Design\"\n      - \"3.4 Effective Discriminable Depth (EDD)\"\n    word_budget: 1000\n    core_bullets:\n      - \"Definition: Given text x, estimate recursive generation depth d ∈ {0,1,...,K}, where d=0 = human-written\"\n      - \"Benchmark: 3 models (Pythia-1.4B, OLMo-1B, GPT-2 XL) × 3 strategies (nucleus p=0.95, temp τ=0.9, top-k k=50) × 4 depths (d0-d3), 5000 samples/cell, total 180k samples\"\n      - \"Pipeline: seed text (OpenWebText/Dolma/WebText) → LoRA finetune → generate → repeat; reference model GPT-2 base (独立于生成模型)\"\n      - \"Features: 19-dim — perplexity statistics (mean/var/skewness/kurtosis/p10/p25/p50/p75/p90 PPL, 9 features), surprisal statistics (mean/var surprisal + entropy_of_surprisal, 3 features), lexical diversity (TTR, hapax ratio, bigram_entropy, trigram_entropy, 4 features), repetition (rep_2gram/rep_3gram/rep_4gram fractions, 3 features)\"\n      - \"EDD: EDD_T = max d* s.t. AUC(d*, d*+1) ≥ T, default T=0.75; report sensitivity at T ∈ {0.65, 0.70, 0.75, 0.80}\"\n      - \"Classifiers: RF(200 trees) primary, CORAL/DivEye/CE-MLP/LR as baselines; single-feature ppl regression as lower bound\"\n      - \"Reference model specification: GPT-2 base (124M), cross-model LOO 时不换 ref model, circularity discussion in §6\"\n    dependencies: []\n    notation_table:\n      d: \"recursive generation depth (d=0 human)\"\n      K: \"maximum depth in benchmark\"\n      EDD_T: \"Effective Discriminable Depth at AUC threshold T\"\n      f_x: \"19-dim statistical feature vector\"\n      M: \"{Pythia-1.4B, OLMo-1B, GPT-2 XL}\"\n      S: \"{nucleus p=0.95, temp τ=0.9, top-k k=50}\"\n    figures: []\n    tables: [tab_features]\n    registry_refs: [mvp_pipeline_pythia_002]\n\n  - section: atlas\n    title: \"The Depth Degradation Atlas\"\n    subsections:\n      - \"4.1 In-Distribution Performance\"\n      - \"4.2 Feature Universality\"\n      - \"4.3 Monotonicity and Inter-Depth Distances\"\n      - \"4.4 EDD Analysis\"\n      - \"4.5 Strategy-Dependent Trajectories\"\n    word_budget: 1200\n    core_bullets:\n      - \"3×3 matrix: 70–85% RF 4-class acc; GPT-2 XL temp09 best (85.4%), Pythia topk50 lowest (69.6%); model and strategy effects are comparable in magnitude (strategy slightly larger: 8.4pp vs 7.1pp)\"\n      - \"Feature universality: p90_ppl top-2 in 9/9 cells (100%), var_surprisal top-2 in 7/9 (78%); cross-model rank correlation mean=0.868 [0.619–0.954]\"\n      - \"Monotonicity: ρ = -0.82 to -0.89; non-uniform inter-depth distances (d0→d1 gap >> d2→d3 gap); feature importance evolves — var_surprisal dominant at shallow, p90_ppl/kurtosis at deep\"\n      - \"EDD: 7/9 cells EDD≥3 at T=0.75; binary pairwise verification EDD=4 (Pythia nucleus: d3v4 AUC=0.784 > 0.75, d4v5 AUC=0.683 < 0.75)\"\n      - \"EDD sensitivity: report at T ∈ {0.65, 0.70, 0.75, 0.80}\"\n      - \"Three-tier strategy classification: nucleus=baseline stable, temperature=signal enhancement BUT d1v2 boundary reversal risk, top-k=signal attenuation but direction preserved\"\n      - \"Temperature reversal mechanism: uniform logit scaling (vs truncation) accelerates convergence to attractor distribution — temp09 depth N features ≈ nucleus/topk50 depth N+1; GPT-2 XL temp09 d1 p90_ppl median=92.2 falls into nucleus/topk50 d2 range 65–92\"\n    dependencies: []\n    tables: [tab_main_matrix, tab_feature_importance]\n    figures: [fig_auc_decay, fig_feature_trajectory, fig_atlas_heatmap]\n    registry_refs:\n      - mvp_pipeline_pythia_002\n      - pythia_temp09_001\n      - pythia_topk50_001\n      - cross_model_olmo_002\n      - olmo_temp09_001\n      - olmo_topk50_001\n      - cross_model_gpt2xl_001\n      - gpt2xl_temp09_001\n      - gpt2xl_topk50_001\n      - atlas_v2_analysis\n      - depth_extension_binary_pairwise_002\n      - depth_extension_pythia_d4d5_001\n\n  - section: generalization\n    title: \"Generalization and Robustness\"\n    subsections:\n      - \"5.1 Baseline Comparison\"\n      - \"5.2 Cross-Model Transfer\"\n      - \"5.3 Cross-Strategy Transfer\"\n      - \"5.4 End-to-End Learning: A Negative Result\"\n    word_budget: 1000\n    core_bullets:\n      - \"Baselines (Pythia nucleus): RF 78.2% ≈ CORAL 78.1% ≈ DivEye 78.2% > CE-MLP 74.9% > LR 75.0% > DeepSeek V3.2 zero-shot 40.0% (200 samples, Pythia nucleus only) >> ppl-regression 25.1% (chance); feature-based methods outperform both LLM zero-shot and single-feature\"\n      - \"Cross-model LOO: mean 66.4% (gate 45% ✓); Pythia 62.4%, OLMo 69.2%, GPT-2 XL 67.6%; depth_0 recall >98% inflates headline — per-class: d2 recall as low as 26.8% (Pythia holdout)\"\n      - \"Cross-strategy LOO: mean 59.1%; nucleus holdout best (65.4–69.4%), topk50 holdout worst (51.5–54.9%); temp09 holdout d1v2 AUC inverts (GPT-2 XL 0.13, OLMo 0.25)\"\n      - \"Z-score normalization: two-layer structure — LR nucleus/topk holdout d1v2 AUC 0.61–0.89 (scale shift, normalization-fixable), BUT temp09 holdout d1v2 AUC remains <0.5 (GPT-2 XL 0.24); RF unchanged (Δ<0.02pp, tree-invariant). Temperature decoding induces qualitatively different feature distributions beyond linear rescaling\"\n      - \"DCOL v1-v6: 6 attempts all failed; v6 RoBERTa-large best 64.5% (vs RF 78.2%), severe overfitting (train 75% vs val 64.4% at epoch 1); embedding collapse (v1-v3), OOM (v4), NaN (v5) → end-to-end contrastive ordinal learning insufficient for text depth\"\n    dependencies: []\n    tables: [tab_baselines, tab_cross_model, tab_cross_strategy]\n    figures: [fig_confusion_matrix]\n    registry_refs:\n      - baseline_battery_001\n      - baseline_battery_9cell_001\n      - cross_model_loo_v1\n      - cross_strategy_loo_001\n      - cross_strategy_loo_zscore_001\n      - dcol_roberta_v6_001\n\n  - section: discussion\n    title: \"Discussion and Limitations\"\n    subsections:\n      - \"6.1 Implications\"\n      - \"6.2 Limitations\"\n    word_budget: 500\n    core_bullets:\n      - \"Depth-graduated curation: predicted depth as finer-grained quality proxy than binary labels (conceptual, empirical validation deferred)\"\n      - \"Feature evolution: var_surprisal→p90_ppl/kurtosis shift from shallow to deep consistent with Shumailov tail erosion theory\"\n      - \"Cross-strategy deployment: 需先验知道目标策略类型, 否则 d1/d2 预测可能反转\"\n      - \"Controlled setting: 固定 seed text + LoRA finetuning + 3 models at 1-1.5B scale; wild-data transfer + 7B+ scale 待验证\"\n      - \"Reference model circularity: GPT-2 base 作为 ref model, cross-model LOO 时 GPT-2 XL holdout 存在 partial overlap — 但 GPT-2 XL holdout 并非最高 (67.6% < OLMo 69.2%)\"\n      - \"Feature domain fragility: Pudasaini et al. 发现 detection features 在 domain shift 下退化, ordinal depth features 可能同样脆弱\"\n    dependencies: [atlas, generalization]\n    citation_hints:\n      - \"bakshi2026: non-monotonic dynamics complicating depth assumption\"\n      - \"dsir2023, qurating2024: data curation context\"\n      - \"marchi2024: temperature convergence theory support\"\n      - \"pudasaini2026: feature fragility under distribution shift\"\n      - \"falahati2026: curated pipelines harder case\"\n      - \"sugiyama2007: covariate shift theory\"\n    figures: []\n    tables: []\n    registry_refs: []\n\n  - section: conclusion\n    word_budget: 200\n    core_bullets:\n      - \"Summary: 定义 recursive depth estimation 任务, 构建 Depth Degradation Atlas, 揭示 universal (p90_ppl/var_surprisal) + strategy-dependent (temperature reversal) 双层信号结构\"\n      - \"Key numbers: 70–85% in-distribution, EDD=4, cross-model 66.4%, cross-strategy 59.1%\"\n      - \"Future: wild-data calibration, 7B+ scale, strategy-conditioned classifiers, depth-graduated curation experiments\"\n    dependencies: [atlas, generalization, discussion]\n    figures: []\n    tables: []\n    registry_refs: []\n\n# ============================================================\n# VISUALIZATION PLAN (≥4 figures, Dream D002 requirement)\n# ============================================================\nvisualization_plan:\n\n  - fig_id: fig_auc_decay\n    type: statistical\n    tool: matplotlib\n    description: \"Pairwise AUC decay curve across adjacent depth pairs (d0v1 → d4v5) with horizontal EDD threshold lines at T=0.65/0.70/0.75/0.80. Show binary pairwise AUC (solid) vs 4-class pipeline AUC (dashed) for Pythia nucleus. Mark EDD=4 crossing point.\"\n    data_source: \"registry: depth_extension_binary_pairwise_002, mvp_pipeline_pythia_002, depth_extension_pythia_d4d5_001\"\n    placement: atlas\n    aspect_ratio: \"4:3\"\n    notes: \"X-axis: depth pair (d0v1, d1v2, d2v3, d3v4, d4v5); Y-axis: AUC; horizontal lines at T thresholds\"\n\n  - fig_id: fig_feature_trajectory\n    type: statistical\n    tool: matplotlib\n    description: \"Feature trajectory panel: top-5 features (p90_ppl, var_surprisal, mean_ppl, mean_surprisal, p75_ppl) median values across depth 0-3, one subplot per model family (3 subplots). Each subplot shows 3 strategies as different line styles. Highlights non-uniform inter-depth distances and temperature reversal.\"\n    data_source: \"registry: atlas_v2_analysis; raw feature data from 9 cell experiments\"\n    placement: atlas\n    aspect_ratio: \"16:5\"\n    notes: \"3-panel figure (Pythia | OLMo | GPT-2 XL). Shared legend. Log-scale y-axis for PPL features.\"\n\n  - fig_id: fig_atlas_heatmap\n    type: statistical\n    tool: matplotlib\n    description: \"Atlas feature importance heatmap: 9-cell grid (3 models × 3 strategies) showing top-5 feature importance values. Color = importance magnitude, cell annotation = rank. Highlights p90_ppl/var_surprisal universality.\"\n    data_source: \"registry: atlas_v2_analysis, baseline_battery_9cell_001\"\n    placement: atlas\n    aspect_ratio: \"4:3\"\n    notes: \"Rows = features (top-5), Columns = 9 cells grouped by model. Okabe-Ito colormap.\"\n\n  - fig_id: fig_confusion_matrix\n    type: statistical\n    tool: matplotlib\n    description: \"Confusion matrix heatmap for best in-distribution setting (GPT-2 XL temp09, 85.4%) and best cross-model LOO setting (OLMo holdout, 69.2%). Two-panel figure showing in-distribution vs transfer performance.\"\n    data_source: \"registry: gpt2xl_temp09_001, cross_model_loo_v1\"\n    placement: generalization\n    aspect_ratio: \"8:3\"\n    notes: \"2-panel. Normalized by true class. Annotate counts + percentages.\"\n\n# ============================================================\n# TABLE PLAN\n# ============================================================\ntable_plan:\n\n  - table_id: tab_main_matrix\n    caption: \"In-distribution 4-class depth estimation accuracy (\\\\%) across 3 model families × 3 decoding strategies. RF classifier, 19 statistical features.\"\n    placement: atlas\n    type: comparison\n    columns: [Model, \"nucleus p=0.95\", \"temp τ=0.9\", \"top-k k=50\"]\n    data_source: \"registry: mvp_pipeline_pythia_002, pythia_temp09_001, pythia_topk50_001, cross_model_olmo_002, olmo_temp09_001, olmo_topk50_001, cross_model_gpt2xl_001, gpt2xl_temp09_001, gpt2xl_topk50_001\"\n    notes: \"Bold best per row. Also include 3-class (d1-d3 only) acc as companion metric (Dream D002 req #5).\"\n\n  - table_id: tab_features\n    caption: \"19 statistical features extracted from reference-model perplexity distributions.\"\n    placement: method\n    type: configuration\n    columns: [Feature, Description, Category]\n    data_source: \"manual\"\n    notes: \"Grouped by category: perplexity stats, surprisal stats, lexical diversity, burstiness. 可移至 appendix 如空间不足.\"\n\n  - table_id: tab_feature_importance\n    caption: \"Top-5 feature importance ranking across 9 benchmark cells. p90_ppl appears in top-2 for all 9 cells.\"\n    placement: atlas\n    type: statistics\n    columns: [Cell, \"Rank 1\", \"Rank 2\", \"Rank 3\", \"Rank 4\", \"Rank 5\"]\n    data_source: \"registry: atlas_v2_analysis\"\n    notes: \"Highlight p90_ppl and var_surprisal entries. 可与 fig_atlas_heatmap 二选一如空间不足.\"\n\n  - table_id: tab_baselines\n    caption: \"Comparison of classification methods on Pythia-1.4B nucleus (baseline setting).\"\n    placement: generalization\n    type: comparison\n    columns: [Method, \"4-class Acc\", \"3-class Acc\", \"d1v2 AUC\", \"d2v3 AUC\"]\n    data_source: \"registry: baseline_battery_001, mvp_pipeline_pythia_002\"\n    notes: \"Methods: RF, CORAL, DivEye, CE-MLP, LR, DeepSeek V3.2 (zero-shot, 200 samples), ppl-regression (single feature).\"\n\n  - table_id: tab_cross_model\n    caption: \"Cross-model leave-one-out generalization. Train on 2 model families, test on held-out 3rd.\"\n    placement: generalization\n    type: comparison\n    columns: [Holdout, \"4-class Acc\", \"d0 Recall\", \"d1 Recall\", \"d2 Recall\", \"d3 Recall\", \"d1v2 AUC\"]\n    data_source: \"registry: cross_model_loo_v1\"\n    notes: \"Report per-class recall to expose d0 inflation. Chance = 25%.\"\n\n  - table_id: tab_cross_strategy\n    caption: \"Cross-strategy leave-one-out transfer. Per-model accuracy when one strategy is held out.\"\n    placement: generalization\n    type: comparison\n    columns: [Holdout, \"Pythia Acc\", \"OLMo Acc\", \"GPT-2 XL Acc\", \"d1v2 AUC (GPT-2 XL)\", \"d1v2 AUC (OLMo)\"]\n    data_source: \"registry: cross_strategy_loo_001, cross_strategy_loo_zscore_001\"\n    notes: \"Highlight temp09 d1v2 AUC inversion (0.13/0.25). Add z-score row for comparison.\"\n\n  - table_id: tab_edd_sensitivity\n    caption: \"EDD at different AUC thresholds (Pythia-1.4B nucleus, binary pairwise).\"\n    placement: atlas\n    type: statistics\n    columns: [Threshold, \"d1v2\", \"d2v3\", \"d3v4\", \"d4v5\", EDD]\n    data_source: \"registry: depth_extension_binary_pairwise_002\"\n    notes: \"Dream D002 requirement #6. Show AUC values at each pair and resulting EDD.\"\n\n# ============================================================\n# LITERATURE STRATEGY\n# ============================================================\nliterature_strategy:\n  citation_budget: 35\n  macro_context:\n    - \"model collapse and recursive generation\"\n    - \"AI-generated text detection\"\n    - \"decoding strategy effects on text properties\"\n    - \"ordinal classification methods\"\n    - \"data curation for LLM training\"\n  micro_clusters:\n    - cluster_name: \"Model Collapse Theory\"\n      search_queries:\n        - \"model collapse recursive generation 2024 2025 2026\"\n        - \"self-consuming generative models iterative training\"\n      must_cite:\n        - \"shumailov2024_nature\"\n        - \"alemohammad2024_mad\"\n        - \"dohmatob2024_tale_of_tails\"\n      target_count: 10\n    - cluster_name: \"AI Text Detection\"\n      search_queries:\n        - \"machine-generated text detection statistical 2024 2025\"\n        - \"zero-shot LLM detection perplexity\"\n      must_cite:\n        - \"binoculars2024\"\n        - \"fast_detectgpt2024\"\n        - \"diveye2026\"\n        - \"gehrmann2019_gltr\"\n      target_count: 8\n    - cluster_name: \"Decoding Strategy Effects\"\n      search_queries:\n        - \"decoding strategy text generation sampling 2024 2025\"\n        - \"nucleus sampling temperature top-k effects\"\n      must_cite:\n        - \"holtzman2020_nucleus\"\n        - \"garces_arias2025_decoding_decoded\"\n      target_count: 5\n    - cluster_name: \"Ordinal Classification\"\n      search_queries:\n        - \"ordinal classification contrastive learning 2024 2025\"\n        - \"CORAL ordinal regression neural networks\"\n      must_cite:\n        - \"coral2020\"\n        - \"cloc2025\"\n      target_count: 3\n    - cluster_name: \"Data Curation & Adjacent\"\n      search_queries:\n        - \"data curation quality scoring LLM training 2024 2025\"\n        - \"AI text editing extent detection\"\n      must_cite:\n        - \"editlens2026\"\n        - \"kirchenbauer2023_watermark\"\n      target_count: 5\n\n# ============================================================\n# WRITING ORDER (strict serial)\n# ============================================================\nwriting_order:\n  - atlas           # Section 4 — PRIMARY contribution, data-driven, write first\n  - generalization   # Section 5 — secondary experiments, depends on atlas narrative\n  - method           # Section 3 — formalize based on what atlas/experiments need\n  - introduction     # Section 1 — frame story around established results\n  - related_work     # Section 2 — position relative to intro framing\n  - discussion       # Section 6 — synthesize, includes limitations\n  - abstract         # condense final narrative\n  - conclusion       # summarize\n\n# ============================================================\n# APPENDIX PLAN\n# ============================================================\nappendix:\n  - \"A: Full 19-feature list with mathematical definitions\"\n  - \"B: Per-class precision/recall/F1 for all 9 in-distribution cells\"\n  - \"C: DCOL training details (hyperparameters, loss curves, failure modes)\"\n  - \"D: Confusion matrices for all 9 cells\"\n  - \"E: Full feature importance rankings\"\n  - \"F: Depth extension 6-class results (d0-d5)\"\n  - \"G: Hyperparameter configurations for benchmark construction\"\n\n# ============================================================\n# WORD BUDGET SUMMARY\n# ============================================================\n# abstract:       150\n# introduction:   900\n# related_work:   600\n# method:        1000\n# atlas:         1200\n# generalization: 1000\n# discussion:     500\n# conclusion:     200\n# ─────────────────\n# Total:         5550 words + 4 figures + 6-7 tables ≈ 8 pages\n",
      "numLines": 398,
      "startLine": 1,
      "totalLines": 398
    }
  },
  "sourceToolAssistantUUID": "5c3ae3f9-178d-48c5-a7aa-eaf81ff4f06e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-15T15:20:56.254Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01XjZzfhWaeVeGZuoybM3Gx8`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f99078e2-8047-4e65-a587-b76919b0af82",
  "isSidechain": false,
  "requestId": "req_011Cb4afWwDoepqafuRe6E9e",
  "type": "assistant",
  "uuid": "1850ba41-c855-4b97-9d3f-3fa4a4c51019",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQF8CnooekXVJBGafyAPS5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19236,
      "cache_read_input_tokens": 11841,
      "output_tokens": 475,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 19236,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 475,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 19236,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 19236
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Runtime record

_source line 20_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Paper Agent 触发审查]: ## 审查请求 — Reviewer Round 2（3处修复）  **writing_plan**: `projects/recursive_gen_depth_est/writing_plan.yaml` **Paper dir**: `projects/recursive_gen_depth_est/docs/paper/` **编译状态**: 11页…",
  "leafUuid": "a8b10988-06ac-4200-b350-33cbffa0635c",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper revisions for recursive depth estimation",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655"
}
```

---

### Assistant

_source line 22 · 2026-05-15T15:21:00.873Z_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the registry to cross-verify numbers, and also check the other files mentioned in the review request. Let me also read the generalization section and discussion/limitations to verify the cross-references.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a8b10988-06ac-4200-b350-33cbffa0635c",
  "isSidechain": false,
  "requestId": "req_011Cb4ag31UzoTuNnEJ6SbW5",
  "type": "assistant",
  "uuid": "01cd138f-2c1a-4247-a893-40b3b0cab05f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015C6mG9WRpRE4rX9MPu9dnr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17139,
      "cache_read_input_tokens": 31077,
      "output_tokens": 330,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17139,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 330,
          "cache_read_input_tokens": 31077,
          "cache_creation_input_tokens": 17139,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17139
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-15T15:21:02.400Z_

读取 registry 交叉验证数字，同时检查 discussion.tex 中的 Limitations 段落（修改1引用目标）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "01cd138f-2c1a-4247-a893-40b3b0cab05f",
  "isSidechain": false,
  "requestId": "req_011Cb4ag31UzoTuNnEJ6SbW5",
  "type": "assistant",
  "uuid": "646085ba-df63-4143-8ac3-f201591a1667",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015C6mG9WRpRE4rX9MPu9dnr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17139,
      "cache_read_input_tokens": 31077,
      "output_tokens": 330,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17139,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 330,
          "cache_read_input_tokens": 31077,
          "cache_creation_input_tokens": 17139,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17139
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-15T15:21:02.914Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01XEy1jV3yNJBqJkZJDih2Xc`</summary>

```json
{
  "project": "recursive_gen_depth_est",
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "646085ba-df63-4143-8ac3-f201591a1667",
  "isSidechain": false,
  "requestId": "req_011Cb4ag31UzoTuNnEJ6SbW5",
  "type": "assistant",
  "uuid": "5533e823-d7f4-4d44-b5ac-5f8971f26bd8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015C6mG9WRpRE4rX9MPu9dnr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17139,
      "cache_read_input_tokens": 31077,
      "output_tokens": 330,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17139,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 330,
          "cache_read_input_tokens": 31077,
          "cache_creation_input_tokens": 17139,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17139
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-15T15:21:05.062Z_

<details><summary>↩ Tool result · `toolu_01NfoRCCrUEH1CX3M2H3z3sc`</summary>

```text
1	\section{Generalization and Robustness}
2	\label{sec:generalization}
3	
4	We test whether the atlas results (69.6--85.4\%) reflect genuine statistical regularities or training artifacts, evaluating four axes: classifier choice (\S\ref{sec:gen:baselines}), cross-model transfer (\S\ref{sec:gen:crossmodel}), cross-strategy transfer (\S\ref{sec:gen:crossstrategy}), and end-to-end learning (\S\ref{sec:gen:dcol}).
5	
6	\subsection{Baseline Comparison}
7	\label{sec:gen:baselines}
8	
9	Table~\ref{tab:baselines} compares classification methods on the Pythia-1.4B nucleus setting.
10	Three feature-based methods---Random Forest (RF), CORAL ordinal regression \cite{coral2020}, and DivEye \cite{diveye2026}---all operate on the same 19 statistical features and achieve statistically indistinguishable accuracy (78.1--78.2\%; pairwise bootstrap $p>0.05$ after Bonferroni correction, 95\% CI within $\pm$1.1pp).
11	These three significantly outperform CE-MLP ($p<0.001$, $+$3.8pp), which in turn trails logistic regression by $\sim$0.1pp.
12	Single-feature regression on mean perplexity performs at chance (25.1\%), confirming that depth estimation requires the multi-dimensional feature representation defined in \S\ref{sec:method}.
13	
14	\begin{table}[t]
15	\centering
16	\small
17	\caption{Comparison of classification methods on Pythia-1.4B nucleus. RF, CORAL, and DivEye use the same 19 statistical features and are statistically indistinguishable (bootstrap $p>0.05$, Bonferroni-corrected). Chance = 25\%. 5-fold CV std: 0.2--0.9pp across all methods.}
18	\label{tab:baselines}
19	\begin{tabular}{lc}
20	\toprule
21	Method & 4-class Acc (\%) \\
22	\midrule
23	RF (19 features) & 78.2 \\
24	CORAL & 78.1 \\
25	DivEye & 78.2 \\
26	CE-MLP & 74.9 \\
27	LR & 75.0 \\
28	DeepSeek V3.2 (zero-shot)\footnotemark & 40.0 \\
29	ppl-regression (single feature) & 25.1 \\
30	\bottomrule
31	\end{tabular}
32	\footnotetext{Evaluated on 200 samples (approximately 50 per class) from the Pythia-1.4B nucleus cell only, due to API cost; 95\% CI: $\pm$6.8pp. All other methods use the full 20{,}000-sample set.}
33	\end{table}
34	
35	That three structurally different classifiers achieve identical performance confirms that the discriminative signal resides in the 19 features, not the classifier architecture; a zero-shot LLM baseline (DeepSeek V3.2) reaches only 40.0\%.
36	Figure~\ref{fig:confusion_matrix} shows d0 is near-perfectly identified in both settings; errors concentrate at the d2/d3 boundary in-distribution and spread across d1--d3 under cross-model transfer.
37	
38	\begin{figure}[t]
39	\centering
40	\includegraphics[width=\columnwidth]{../../figures/paper/fig_confusion_matrix.pdf}
41	\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\tau{=}0.9$, 85.4\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\%). d0 recall exceeds 99\% in both; errors spread across the d1--d3 range under transfer.}
42	\label{fig:confusion_matrix}
43	\end{figure}
44	
45	\subsection{Cross-Model Transfer}
46	\label{sec:gen:crossmodel}
47	
48	We perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\ref{tab:cross_model}).
49	
50	\begin{table}[t]
51	\centering
52	\small
53	\caption{Cross-model transfer (leave-one-out, nucleus only). Train on 2 model families, test on held-out 3rd. Chance = 25\%.}
54	\label{tab:cross_model}
55	\begin{tabular}{lccccc}
56	\toprule
57	Holdout & Acc & d0 & d1 & d2 & d3 \\
58	 & (\%) & Rec. & Rec. & Rec. & Rec. \\
59	\midrule
60	Pythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\
61	OLMo & \textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\
62	GPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\
63	\midrule
64	Mean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\
65	\bottomrule
66	\end{tabular}
67	\end{table}
68	
69	Mean transfer accuracy reaches 66.4\% (2.7$\times$ chance), though d0 recall ($>$98\%) inflates the headline; d2 recall drops to 26.8\% (Pythia holdout), making it the most confusable class.
70	
71	\subsection{Cross-Strategy Transfer}
72	\label{sec:gen:crossstrategy}
73	
74	We train on two decoding strategies and test on the held-out third (Table~\ref{tab:cross_strategy}).
75	
76	\begin{table}[t]
77	\centering
78	\small
79	\caption{Cross-strategy transfer (leave-one-out). Train on 2 strategies, test on held-out 3rd. Chance = 25\%.}
80	\label{tab:cross_strategy}
81	\begin{tabular}{lccc}
82	\toprule
83	Holdout & Pythia & OLMo & GPT-2 XL \\
84	 & Acc (\%) & Acc (\%) & Acc (\%) \\
85	\midrule
86	nucleus & \textbf{69.4} & \textbf{65.4} & \textbf{59.9} \\
87	temp ($\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\
88	top-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\
89	\bottomrule
90	\end{tabular}
91	\end{table}
92	
93	Mean cross-strategy accuracy (59.1\%) falls 7 points below cross-model transfer (66.4\%), indicating that strategy-induced distribution shifts pose a greater generalization challenge than architectural differences.
94	As with cross-model transfer, d0 recall remains high ($\geq$89.5\%) across all holdout settings, inflating the headline accuracy; d2 recall ranges from 3.7\% to 19\%, confirming mid-chain depths as the primary confusion locus across both transfer axes.
95	
96	\paragraph{Temperature-induced boundary inversion.}
97	Training on nucleus + top-$k$ and testing on temperature yields d1v2 AUC of 0.129 for GPT-2~XL and 0.253 for OLMo---both below 0.5, indicating that the d1/d2 decision boundary \emph{inverts} (Pythia retains a degraded 0.576), consistent with the accelerated convergence in \S\ref{sec:atlas:trajectories}.
98	Z-score normalization \cite{sugiyama2007_importance_weighting} improves logistic regression cross-strategy accuracy (25\%$\to$61\%) but does not recover the inversion---all three models worsen (GPT-2~XL 0.50$\to$0.24, OLMo 0.50$\to$0.19, Pythia 0.63$\to$0.52)---confirming a genuine geometry-level shift rather than a correctable scale difference.
99	
100	\subsection{End-to-End Learning}
101	\label{sec:gen:dcol}
102	
103	We finetune DeBERTa-v3-base and RoBERTa-base end-to-end (lr$\,{=}\,2{\times}10^{-5}$, 3 epochs, 5-fold CV) on Pythia-1.4B nucleus data.
104	Both converge to ${\sim}$59\% (RoBERTa 59.5$\pm$3.2\%, DeBERTa 58.3$\pm$4.7\%), 19pp below feature-based RF (78.2\%); the 1.2pp inter-backbone gap rules out architecture selection bias.
105	Both easily separate d0 (F1$>$0.95) but fail at adjacent-depth discrimination (d1/d2 F1$<$0.42).
106	Probing reveals a negative correlation between PLM attention and RF permutation importance for both backbones (DeBERTa $\rho{=}{-}0.484$, RoBERTa $\rho{=}{-}0.456$; zero top-5 overlap; Appendix~\ref{app:feature_overlap}), confirming that PLMs encode surface lexical cues while our features capture perplexity tail structure inaccessible to end-to-end learning.
107	
108	DCOL \cite{cloc2025}, which adds a contrastive ordinal loss, fared worse: across six iterations with two backbones (Appendix~\ref{app:dcol_iterations}), the best run (RoBERTa-large) reached only 64.5\% with severe overfitting, 13.7pp below RF.
109	That all end-to-end approaches---standard finetuning (58--60\%), DCOL (64.5\%)---substantially underperform feature-based methods (78.2\%) confirms that depth estimation requires explicit distributional statistics rather than learned text representations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f2dd80b1-e80a-4b5b-b278-b4cee310b954",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "d2c97c11-2194-46db-b83d-796bb503df33",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
      "content": "\\section{Generalization and Robustness}\n\\label{sec:generalization}\n\nWe test whether the atlas results (69.6--85.4\\%) reflect genuine statistical regularities or training artifacts, evaluating four axes: classifier choice (\\S\\ref{sec:gen:baselines}), cross-model transfer (\\S\\ref{sec:gen:crossmodel}), cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}), and end-to-end learning (\\S\\ref{sec:gen:dcol}).\n\n\\subsection{Baseline Comparison}\n\\label{sec:gen:baselines}\n\nTable~\\ref{tab:baselines} compares classification methods on the Pythia-1.4B nucleus setting.\nThree feature-based methods---Random Forest (RF), CORAL ordinal regression \\cite{coral2020}, and DivEye \\cite{diveye2026}---all operate on the same 19 statistical features and achieve statistically indistinguishable accuracy (78.1--78.2\\%; pairwise bootstrap $p>0.05$ after Bonferroni correction, 95\\% CI within $\\pm$1.1pp).\nThese three significantly outperform CE-MLP ($p<0.001$, $+$3.8pp), which in turn trails logistic regression by $\\sim$0.1pp.\nSingle-feature regression on mean perplexity performs at chance (25.1\\%), confirming that depth estimation requires the multi-dimensional feature representation defined in \\S\\ref{sec:method}.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Comparison of classification methods on Pythia-1.4B nucleus. RF, CORAL, and DivEye use the same 19 statistical features and are statistically indistinguishable (bootstrap $p>0.05$, Bonferroni-corrected). Chance = 25\\%. 5-fold CV std: 0.2--0.9pp across all methods.}\n\\label{tab:baselines}\n\\begin{tabular}{lc}\n\\toprule\nMethod & 4-class Acc (\\%) \\\\\n\\midrule\nRF (19 features) & 78.2 \\\\\nCORAL & 78.1 \\\\\nDivEye & 78.2 \\\\\nCE-MLP & 74.9 \\\\\nLR & 75.0 \\\\\nDeepSeek V3.2 (zero-shot)\\footnotemark & 40.0 \\\\\nppl-regression (single feature) & 25.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\footnotetext{Evaluated on 200 samples (approximately 50 per class) from the Pythia-1.4B nucleus cell only, due to API cost; 95\\% CI: $\\pm$6.8pp. All other methods use the full 20{,}000-sample set.}\n\\end{table}\n\nThat three structurally different classifiers achieve identical performance confirms that the discriminative signal resides in the 19 features, not the classifier architecture; a zero-shot LLM baseline (DeepSeek V3.2) reaches only 40.0\\%.\nFigure~\\ref{fig:confusion_matrix} shows d0 is near-perfectly identified in both settings; errors concentrate at the d2/d3 boundary in-distribution and spread across d1--d3 under cross-model transfer.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_confusion_matrix.pdf}\n\\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\\tau{=}0.9$, 85.4\\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\\%). d0 recall exceeds 99\\% in both; errors spread across the d1--d3 range under transfer.}\n\\label{fig:confusion_matrix}\n\\end{figure}\n\n\\subsection{Cross-Model Transfer}\n\\label{sec:gen:crossmodel}\n\nWe perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\\ref{tab:cross_model}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model transfer (leave-one-out, nucleus only). Train on 2 model families, test on held-out 3rd. Chance = 25\\%.}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nHoldout & Acc & d0 & d1 & d2 & d3 \\\\\n & (\\%) & Rec. & Rec. & Rec. & Rec. \\\\\n\\midrule\nPythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\\\\nOLMo & \\textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\\\\nGPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\\\\n\\midrule\nMean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean transfer accuracy reaches 66.4\\% (2.7$\\times$ chance), though d0 recall ($>$98\\%) inflates the headline; d2 recall drops to 26.8\\% (Pythia holdout), making it the most confusable class.\n\n\\subsection{Cross-Strategy Transfer}\n\\label{sec:gen:crossstrategy}\n\nWe train on two decoding strategies and test on the held-out third (Table~\\ref{tab:cross_strategy}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-strategy transfer (leave-one-out). Train on 2 strategies, test on held-out 3rd. Chance = 25\\%.}\n\\label{tab:cross_strategy}\n\\begin{tabular}{lccc}\n\\toprule\nHoldout & Pythia & OLMo & GPT-2 XL \\\\\n & Acc (\\%) & Acc (\\%) & Acc (\\%) \\\\\n\\midrule\nnucleus & \\textbf{69.4} & \\textbf{65.4} & \\textbf{59.9} \\\\\ntemp ($\\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\\\\ntop-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean cross-strategy accuracy (59.1\\%) falls 7 points below cross-model transfer (66.4\\%), indicating that strategy-induced distribution shifts pose a greater generalization challenge than architectural differences.\nAs with cross-model transfer, d0 recall remains high ($\\geq$89.5\\%) across all holdout settings, inflating the headline accuracy; d2 recall ranges from 3.7\\% to 19\\%, confirming mid-chain depths as the primary confusion locus across both transfer axes.\n\n\\paragraph{Temperature-induced boundary inversion.}\nTraining on nucleus + top-$k$ and testing on temperature yields d1v2 AUC of 0.129 for GPT-2~XL and 0.253 for OLMo---both below 0.5, indicating that the d1/d2 decision boundary \\emph{inverts} (Pythia retains a degraded 0.576), consistent with the accelerated convergence in \\S\\ref{sec:atlas:trajectories}.\nZ-score normalization \\cite{sugiyama2007_importance_weighting} improves logistic regression cross-strategy accuracy (25\\%$\\to$61\\%) but does not recover the inversion---all three models worsen (GPT-2~XL 0.50$\\to$0.24, OLMo 0.50$\\to$0.19, Pythia 0.63$\\to$0.52)---confirming a genuine geometry-level shift rather than a correctable scale difference.\n\n\\subsection{End-to-End Learning}\n\\label{sec:gen:dcol}\n\nWe finetune DeBERTa-v3-base and RoBERTa-base end-to-end (lr$\\,{=}\\,2{\\times}10^{-5}$, 3 epochs, 5-fold CV) on Pythia-1.4B nucleus data.\nBoth converge to ${\\sim}$59\\% (RoBERTa 59.5$\\pm$3.2\\%, DeBERTa 58.3$\\pm$4.7\\%), 19pp below feature-based RF (78.2\\%); the 1.2pp inter-backbone gap rules out architecture selection bias.\nBoth easily separate d0 (F1$>$0.95) but fail at adjacent-depth discrimination (d1/d2 F1$<$0.42).\nProbing reveals a negative correlation between PLM attention and RF permutation importance for both backbones (DeBERTa $\\rho{=}{-}0.484$, RoBERTa $\\rho{=}{-}0.456$; zero top-5 overlap; Appendix~\\ref{app:feature_overlap}), confirming that PLMs encode surface lexical cues while our features capture perplexity tail structure inaccessible to end-to-end learning.\n\nDCOL \\cite{cloc2025}, which adds a contrastive ordinal loss, fared worse: across six iterations with two backbones (Appendix~\\ref{app:dcol_iterations}), the best run (RoBERTa-large) reached only 64.5\\% with severe overfitting, 13.7pp below RF.\nThat all end-to-end approaches---standard finetuning (58--60\\%), DCOL (64.5\\%)---substantially underperform feature-based methods (78.2\\%) confirms that depth estimation requires explicit distributional statistics rather than learned text representations.",
      "numLines": 109,
      "startLine": 1,
      "totalLines": 109
    }
  },
  "sourceToolAssistantUUID": "f2dd80b1-e80a-4b5b-b278-b4cee310b954",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-15T15:21:03.855Z_

<details><summary>↩ Tool result · `toolu_01XEy1jV3yNJBqJkZJDih2Xc`</summary>

```text
Error: result (54,604 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-reviewer-2647e3b4/6797ed9c-81cb-4a78-af4b-6d104e682655/tool-results/mcp-agent-ml-research-read_registry-1778858463839.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-reviewer-2647e3b4/6797ed9c-81cb-4a78-af4b-6d104e682655/tool-results/mcp-agent-ml-research-read_registry-1778858463839.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "5533e823-d7f4-4d44-b5ac-5f8971f26bd8",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "6ca89540-3e58-4d3c-9473-a5bd3fa4ec72",
  "toolUseResult": "Error: result (54,604 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-reviewer-2647e3b4/6797ed9c-81cb-4a78-af4b-6d104e682655/tool-results/mcp-agent-ml-research-read_registry-1778858463839.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-reviewer-2647e3b4/6797ed9c-81cb-4a78-af4b-6d104e682655/tool-results/mcp-agent-ml-research-read_registry-1778858463839.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"n2_roberta_finetune_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T12:12:32.982Z\", \"updated_at\": \"2026-05-15T13:28:39.437Z\", \"hypothesis\": \"N2 reviewer concern: end-to-end RoBERTa-base finetune baseline vs RF on hand-crafted features (78.2%). 与 DeBERTa 形成双 backbone 对比，排除模型选择偏差。\", \"notes\": \"5-fold CV 完成 (retry_count=2)。RoBERTa-base 4-class acc=59.5% ± 3.2%，远低于 RF 78.2% (-18.7pp)。Feature overlap: Spearman ρ=-0.456 (p=0.050)，与 DeBERTa (ρ=-0.484) 一致，top-5 overlap=0。跨架构确认 transformer 表征偏向表面特征，perplexity 分布统计量是盲区。var_ppl R²=-4215.8（极端负值）。\", \"conclusion\": \"success\", \"metrics\": {\"accuracy_mean\": 0.5948, \"accuracy_std\": 0.0324, \"per_class_f1\": {\"d0\": 0.958, \"d1\": 0.4161, \"d2\": 0.2611, \"d3\": 0.6472}, \"per_class_precision\": {\"d0\": 0.9983, \"d1\": 0.7178, \"d2\": 0.2956, \"d3\": 0.4958}, \"per_class_recall\": {\"d0\": 0.9208, \"d1\": 0.293, \"d2\": 0.2338, \"d3\": 0.9314}, \"pairwise_auc\": {\"d0v1\": 0.9886, \"d1v2\": 0.7522, \"d2v3\": 0.7349}, \"fold_accuracies\": [0.6022, 0.5595, 0.5623, 0.6018, 0.648], \"vs_rf_baseline\": \"-18.7pp (59.5% vs 78.2%)\", \"vs_deberta\": \"+1.2pp acc, +0.019 d1v2_auc, -0.020 d2v3_auc\", \"elapsed_seconds\": 1942.5}}, \"n2_deberta_finetune_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T12:12:06.592Z\", \"updated_at\": \"2026-05-15T13:20:47.219Z\", \"hypothesis\": \"N2 reviewer concern: end-to-end DeBERTa-v3-base finetune baseline vs RF on hand-crafted features (78.2%). 若 DeBERTa acc < RF，证明手工特征确有独立贡献；若 ≥ RF，需重新定位 narrative。\", \"conclusion\": \"success\", \"metrics\": {\"accuracy_mean\": 0.5831, \"accuracy_std\": 0.0467, \"per_class_f1\": {\"d0\": 0.947, \"d1\": 0.378, \"d2\": 0.247, \"d3\": 0.656}, \"pairwise_auc\": {\"d0v1\": 0.981, \"d1v2\": 0.733, \"d2v3\": 0.755}, \"vs_rf_baseline\": \"58.3% vs 78.2% (-19.9pp)\", \"elapsed_seconds\": 3727}, \"notes\": \"5-fold CV 完成。DeBERTa-v3-base 4-class acc=58.3% ± 4.7%，远低于 RF 78.2% (-19.9pp)。Feature overlap analysis: Spearman ρ=-0.484 (p=0.036)，DeBERTa 和 RF 关注的特征几乎完全相反。DeBERTa 擅长编码表面特征 (TTR R²=0.85, rep_2gram R²=0.82)，而 RF 依赖的 perplexity 分布统计量 (var_surprisal, p90_ppl) 在 DeBERTa 表征中 R² 为负。Top-5 overlap=0。\"}, \"cross_strategy_loo_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T04:12:49.407Z\", \"updated_at\": \"2026-05-15T12:29:21.290Z\", \"hypothesis\": \"Cross-strategy LOO (plan_007): 深度信号跨策略可迁移——同模型内，用 2 种解码策略训练的 RF 可泛化到第 3 种，4-class acc 均值 59.1% 远超 chance 25%。temp09 holdout 的 d1v2 AUC 反转 (GPT-2 XL: 0.13, OLMo: 0.25) 证明解码策略塑造不同的退化轨迹 (D014)\", \"conclusion\": \"success\", \"metrics\": {\"mean_4class_acc\": 0.5908, \"pythia_holdout_nucleus\": {\"acc\": 0.6935, \"d1v2_auc\": 0.6903, \"d2v3_auc\": 0.7626}, \"pythia_holdout_temp09\": {\"acc\": 0.6281, \"d1v2_auc\": 0.576, \"d2v3_auc\": 0.724}, \"pythia_holdout_topk50\": {\"acc\": 0.5151, \"d1v2_auc\": 0.6393, \"d2v3_auc\": 0.5801}, \"gpt2xl_holdout_nucleus\": {\"acc\": 0.5993, \"d1v2_auc\": 0.7826, \"d2v3_auc\": 0.4985}, \"gpt2xl_holdout_temp09\": {\"acc\": 0.5609, \"d1v2_auc\": 0.1288, \"d2v3_auc\": 0.6366}, \"gpt2xl_holdout_topk50\": {\"acc\": 0.5364, \"d1v2_auc\": 0.8308, \"d2v3_auc\": 0.7222}, \"olmo_holdout_nucleus\": {\"acc\": 0.6538, \"d1v2_auc\": 0.7931, \"d2v3_auc\": 0.6076}, \"olmo_holdout_temp09\": {\"acc\": 0.5816, \"d1v2_auc\": 0.2529, \"d2v3_auc\": 0.7015}, \"olmo_holdout_topk50\": {\"acc\": 0.5488, \"d1v2_auc\": 0.8549, \"d2v3_auc\": 0.7107}, \"finding_temp09_d1v2_inversion\": \"d1v2 AUC inverts when holding out temp09 (GPT-2 XL: 0.13, OLMo: 0.25) — temp09 d1→d2 features differ fundamentally from nucleus/topk50\"}, \"notes\": \"Cross-strategy LOO 9/9 > chance, mean 59.1%。temp09 d1v2 AUC 反转（GPT-2 XL: 0.13, OLMo: 0.25）已解释为 Covariate Shift：temperature=0.9 均匀缩放 logit 分布（非截断），模型递归时更快收敛到 attractor 分布，导致 temp09 depth N 的统计特征 ≈ nucleus/topk50 depth N+1。证据：(1) 混淆矩阵显示系统性深度高估（temp09 d1→d2/d3 52%+25%，d2→d3 96%）；(2) 组内 d1v2 AUC 正常（0.94/0.90/0.83）。详见 artifacts/temp09_d1v2_inversion_analysis.md。注：D021 已推翻 z-score 标准化后 AUC 恢复的 claim（LR cross-strategy 降级为 RF-only finding）。\"}, \"depth_extension_olmo_d4d5_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T10:34:26.348Z\", \"updated_at\": \"2026-05-15T12:11:17.988Z\", \"notes\": \"OLMo depth extension Step 5-7 恢复执行（depth_extension_olmo_d4d5_001 因 CUDA device mismatch 在 Step 5 失败）。数据/checkpoint 复用 001 的产出。修复：--gpu 1→0（CUDA_VISIBLE_DEVICES=1 下逻辑设备为 cuda:0）。脚本：resume_olmo_step5.sh。预计 ~35 分钟。\", \"hypothesis\": \"OLMo-1B EDD 与 Pythia-1.4B 一致（EDD=4），验证 EDD 跨模型稳定性\", \"conclusion\": \"success\", \"metrics\": {\"binary_pairwise\": {\"d1v2_auc\": 0.968, \"d2v3_auc\": 0.843, \"d3v4_auc\": 0.765, \"d4v5_auc\": 0.684}, \"six_class_rf_accuracy\": 0.667, \"edd_at_075\": 4, \"edd_note\": \"d3v4=0.765>=0.75 PASS, d4v5=0.684<0.75 FAIL → EDD=4\"}}, \"depth_extension_gpt2xl_d4d5_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:32:10.348Z\", \"updated_at\": \"2026-05-15T12:11:15.829Z\", \"hypothesis\": \"GPT-2 XL depth extension: 从 d3 checkpoint 继续递归生成 d4/d5 各 5000 samples，binary pairwise RF 验证 EDD。GPT-2 XL 是 3×3 矩阵中信号最强的模型 (85.4%)，若 EDD≥4 则与 Pythia 结果 (EDD=4) 形成跨模型 EDD 一致性证据。\", \"parent\": \"cross_model_gpt2xl_001\", \"notes\": \"**代码准备完成 (2026-05-15)**\\n\\n## 文件路径\\n- **GPT-2 XL d3 checkpoint**: `checkpoints/gpt2xl/lora_depth_2/` (用于生成 d3；尚无 lora_depth_3，需先 finetune d3 数据)\\n- **d0-d3 数据**: `data/gpt2xl/depth_{0,1,2,3}.jsonl` (各 5000 samples)\\n- **d0-d3 特征**: `data/gpt2xl/features.jsonl` (20000 samples, evaluator=GPT-2 XL)\\n- **Pipeline 脚本**: `scripts/run_depth_extension_gpt2xl.sh`\\n- **模型路径**: `/root/autodl-tmp/models/gpt2-xl`\\n- **LoRA config**: r=16, alpha=32, dropout=0.05, target=c_attn,c_proj\\n\\n## Pipeline 步骤\\n1. finetune d3 → lora_depth_3 (如已存在则跳过)\\n2. generate d4 (5000 samples, nucleus p=0.95, seed=42)\\n3. finetune d4 → lora_depth_4\\n4. generate d5 (5000 samples)\\n5. extract_features d0-d5 (evaluator=GPT-2 XL, 6-class)\\n6. train_classifier (6-class RF/LR)\\n7. binary_pairwise_eval (d1v2, d2v3, d3v4, d4v5)\\n\\n## 预估运行时间\\n- finetune × 2: ~6 min\\n- generate × 2: ~116 min (58 min/轮)\\n- feature extraction: ~20 min\\n- eval: ~2 min\\n- **总计: ~2.5 小时**\\n\\n## Dry-run 验证结果\\n- 4 个脚本 --help 全部正常\\n- binary_pairwise_eval.py 已修改支持 --features_path/--output_dir\\n- 在 d0-d3 特征上测试通过: d1v2 AUC=0.9574, d2v3 AUC=0.887 (binary RF)\\n- bash -n 语法检查通过\\n\\n## 基线参考 (GPT-2 XL binary pairwise d0-d3)\\n- d1v2: 0.9574 [0.9499, 0.9648]\\n- d2v3: 0.8870 [0.8724, 0.9007]\\n- 高于 Pythia d1v2=0.925, d2v3=0.823，确认 GPT-2 XL 信号最强\\n\\n## 风险\\n- GPT-2 XL 1.5B 比 Pythia 1.4B 稍大，生成速度接近但内存略高，单卡 RTX 6000 Pro (48GB) 足够\\n- d4/d5 生成占用 GPU 0 约 2 小时，需确认不与其他实验冲突\", \"conclusion\": \"success\", \"metrics\": {\"binary_pairwise\": {\"d1v2_auc\": 0.966, \"d2v3_auc\": 0.919, \"d3v4_auc\": 0.75, \"d4v5_auc\": 0.681}, \"six_class_rf_accuracy\": 0.679, \"edd_at_075\": 4, \"edd_note\": \"d3v4=0.750>=0.75 PASS, d4v5=0.681<0.75 FAIL → EDD=4\"}}, \"depth_extension_olmo_d4d5_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T09:23:04.007Z\", \"updated_at\": \"2026-05-15T10:30:31.681Z\", \"hypothesis\": \"OLMo-1B depth extension: 从 d3 checkpoint 继续递归生成 d4/d5 各 5000 samples，binary pairwise RF 验证 EDD。OLMo 是 3×3 矩阵中间模型 (78.8%)，若 EDD≥4 则与 Pythia (EDD=4) 形成跨模型 EDD 一致性证据，3 模型 EDD 完整对比。\", \"parent\": \"cross_model_olmo_002\", \"notes\": \"**失败诊断 (2026-05-15)**\\nRoot cause: extract_features.py 硬编码 device=cuda:1，但 submit_training_job 注入 CUDA_VISIBLE_DEVICES=1 后逻辑上只有 cuda:0 可见。torch.AcceleratorError: CUDA error: invalid device ordinal.\\nPipeline 进度: Step 1-4 全部完成（d4/d5 各 5000 samples 已生成），Step 5 feature extraction 崩溃。\\nError type: infrastructure (device ordinal mismatch)\\nFix: 修改 run_depth_extension_olmo.sh 中 extract_features / train_classifier / binary_pairwise 步骤的 device 参数为 cuda:0（或动态检测），从 Step 5 开始恢复执行。\", \"conclusion\": \"failed\"}, \"lr_zscore_cross_strategy_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T09:41:05.302Z\", \"updated_at\": \"2026-05-15T09:44:47.081Z\", \"hypothesis\": \"LR cross-strategy LOO + z-score: 验证 paper_framing 声称的 z-score 恢复 LR d1v2 AUC（GPT-2 XL 0.13→0.68, OLMo 0.25→0.83）。论文 claim 硬依赖。\", \"parent\": \"cross_strategy_loo_zscore_001\", \"conclusion\": \"negative\", \"metrics\": {\"raw_lr\": {\"mean_acc\": 0.25, \"note\": \"lbfgs convergence failure on unscaled features, all predictions random\", \"pythia_temp09\": {\"acc\": 0.25, \"d1v2_auc\": 0.6313}, \"gpt2xl_temp09\": {\"acc\": 0.25, \"d1v2_auc\": 0.5}, \"olmo_temp09\": {\"acc\": 0.25, \"d1v2_auc\": 0.5}}, \"zscore_lr\": {\"mean_acc\": 0.6081, \"mean_d1v2\": 0.6417, \"pythia_temp09\": {\"acc\": 0.6139, \"d1v2_auc\": 0.5201}, \"gpt2xl_temp09\": {\"acc\": 0.5642, \"d1v2_auc\": 0.2386}, \"olmo_temp09\": {\"acc\": 0.5546, \"d1v2_auc\": 0.1922}, \"pythia_nucleus\": {\"acc\": 0.6425, \"d1v2_auc\": 0.6142}, \"gpt2xl_nucleus\": {\"acc\": 0.7397, \"d1v2_auc\": 0.8851}, \"olmo_nucleus\": {\"acc\": 0.748, \"d1v2_auc\": 0.8627}, \"pythia_topk50\": {\"acc\": 0.5261, \"d1v2_auc\": 0.7711}, \"gpt2xl_topk50\": {\"acc\": 0.5352, \"d1v2_auc\": 0.8214}, \"olmo_topk50\": {\"acc\": 0.5484, \"d1v2_auc\": 0.8696}}, \"paper_claim_vs_actual\": {\"gpt2xl_temp09_d1v2\": {\"paper_raw\": 0.13, \"paper_zscore\": 0.68, \"actual_raw\": 0.5, \"actual_zscore\": 0.2386}, \"olmo_temp09_d1v2\": {\"paper_raw\": 0.25, \"paper_zscore\": 0.83, \"actual_raw\": 0.5, \"actual_zscore\": 0.1922}}}}, \"granularity_ablation_rf_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T09:17:27.738Z\", \"updated_at\": \"2026-05-15T09:30:03.303Z\", \"hypothesis\": \"Granularity ablation: 对比 binary/3-class/4-class/6-class RF 性能，量化分类粒度对决策边界稀释的影响。预期 accuracy 随粒度增加单调下降，adjacent-pair AUC 在 binary 设置下最高。支持 Claim 1 (feasibility) + Claim 2 (EDD boundary dilution)。\", \"parent\": \"baseline_battery_9cell_001\", \"notes\": \"## 脚本准备完成，等待审批\\n\\n### 脚本路径\\n`/root/autodl-tmp/recursive_gen_depth_est/src/granularity_ablation.py`\\n\\n### 运行命令\\n```bash\\ncd /root/autodl-tmp/recursive_gen_depth_est && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python src/granularity_ablation.py\\n```\\n\\n### 9 Cells 特征文件路径\\n| Cell | Path |\\n|------|------|\\n| pythia_nucleus095 | data/features_all.jsonl (20000 samples, d0-d3) |\\n| pythia_temp09 | data/pythia_temp09/features.jsonl |\\n| pythia_topk50 | results/pythia_topk50/features.jsonl |\\n| gpt2xl_nucleus095 | data/gpt2xl/features.jsonl |\\n| gpt2xl_temp09 | results/gpt2xl_temp09/features.jsonl |\\n| gpt2xl_topk50 | results/gpt2xl_topk50/features.jsonl |\\n| olmo_nucleus095 | data/olmo/features.jsonl |\\n| olmo_temp09 | results/olmo_temp09/features.jsonl |\\n| olmo_topk50 | results/olmo_topk50/features.jsonl |\\n\\n### 6-class 数据路径\\n`results/pythia_depth_extension/features_6class.jsonl` (30000 samples, 5000/depth, d0-d5, Pythia nucleus only)\\n\\n### Dry-run 结果 (pythia_nucleus095 only)\\n| Setting | #Cls | Acc | 95% CI | Adjacent AUCs |\\n|---------|------|-----|--------|---------------|\\n| binary | 2 | 0.9980 | [0.9965, 0.9992] | d0v1=1.000 |\\n| 3class | 3 | 0.7117 | [0.6947, 0.7283] | d1v2=0.861, d2v3=0.796 |\\n| 4class | 4 | 0.7812 | [0.7677, 0.7935] | d0v1=0.998, d1v2=0.868, d2v3=0.804 |\\n| 6class | 6 | 0.6292 | [0.6175, 0.6412] | d0v1=0.997, d1v2=0.830, d2v3=0.689, d3v4=0.692, d4v5=0.691 |\\n\\n决策边界稀释效应明显：accuracy 从 binary 99.8% → 4-class 78.1% → 6-class 62.9%；d2v3 AUC 从 3-class 0.796 降至 6-class 0.689。\", \"metrics\": {\"summary\": {\"binary_acc_mean\": 0.995, \"binary_acc_std\": 0.004, \"3class_acc_mean\": 0.721, \"3class_acc_std\": 0.067, \"4class_acc_mean\": 0.783, \"4class_acc_std\": 0.048, \"6class_acc\": 0.629, \"note\": \"3-class excludes d0 (most separable class), so 3class < 4class is by design. True granularity trend (with d0): binary 99.5% > 4-class 78.3% > 6-class 62.9% — monotonic decrease confirmed.\"}, \"per_cell\": {\"pythia_nucleus095\": {\"binary\": {\"acc\": 0.998, \"ci95\": [0.9965, 0.9992], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.7117, \"ci95\": [0.6947, 0.7283], \"auc\": {\"d1v2\": 0.861, \"d2v3\": 0.796}}, \"4class\": {\"acc\": 0.7812, \"ci95\": [0.7677, 0.7935], \"auc\": {\"d0v1\": 0.998, \"d1v2\": 0.868, \"d2v3\": 0.804}}, \"6class\": {\"acc\": 0.6292, \"ci95\": [0.6175, 0.6412], \"auc\": {\"d0v1\": 0.997, \"d1v2\": 0.83, \"d2v3\": 0.689, \"d3v4\": 0.692, \"d4v5\": 0.691}}}, \"pythia_temp09\": {\"binary\": {\"acc\": 0.997, \"ci95\": [0.9952, 0.9985], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.7063, \"ci95\": [0.6907, 0.723], \"auc\": {\"d1v2\": 0.838, \"d2v3\": 0.806}}, \"4class\": {\"acc\": 0.7605, \"ci95\": [0.7475, 0.7738], \"auc\": {\"d0v1\": 0.997, \"d1v2\": 0.835, \"d2v3\": 0.796}}}, \"pythia_topk50\": {\"binary\": {\"acc\": 0.9945, \"ci95\": [0.992, 0.9965], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.5883, \"ci95\": [0.5717, 0.6073], \"auc\": {\"d1v2\": 0.749, \"d2v3\": 0.705}}, \"4class\": {\"acc\": 0.6943, \"ci95\": [0.6805, 0.708], \"auc\": {\"d0v1\": 0.994, \"d1v2\": 0.761, \"d2v3\": 0.695}}}, \"gpt2xl_nucleus095\": {\"binary\": {\"acc\": 0.9912, \"ci95\": [0.9882, 0.9938], \"auc\": {\"d0v1\": 0.999}}, \"3class\": {\"acc\": 0.79, \"ci95\": [0.775, 0.8047], \"auc\": {\"d1v2\": 0.913, \"d2v3\": 0.891}}, \"4class\": {\"acc\": 0.8393, \"ci95\": [0.8283, 0.8502], \"auc\": {\"d0v1\": 0.995, \"d1v2\": 0.916, \"d2v3\": 0.885}}}, \"gpt2xl_temp09\": {\"binary\": {\"acc\": 0.9978, \"ci95\": [0.9962, 0.999], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.826, \"ci95\": [0.8117, 0.8397], \"auc\": {\"d1v2\": 0.944, \"d2v3\": 0.887}}, \"4class\": {\"acc\": 0.8552, \"ci95\": [0.844, 0.866], \"auc\": {\"d0v1\": 0.997, \"d1v2\": 0.939, \"d2v3\": 0.886}}}, \"gpt2xl_topk50\": {\"binary\": {\"acc\": 0.9952, \"ci95\": [0.993, 0.9972], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.695, \"ci95\": [0.6777, 0.7113], \"auc\": {\"d1v2\": 0.844, \"d2v3\": 0.766}}, \"4class\": {\"acc\": 0.757, \"ci95\": [0.743, 0.7702], \"auc\": {\"d0v1\": 0.993, \"d1v2\": 0.824, \"d2v3\": 0.762}}}, \"olmo_nucleus095\": {\"binary\": {\"acc\": 0.9868, \"ci95\": [0.9832, 0.99], \"auc\": {\"d0v1\": 0.999}}, \"3class\": {\"acc\": 0.7503, \"ci95\": [0.7353, 0.7657], \"auc\": {\"d1v2\": 0.873, \"d2v3\": 0.831}}, \"4class\": {\"acc\": 0.7897, \"ci95\": [0.7772, 0.8027], \"auc\": {\"d0v1\": 0.985, \"d1v2\": 0.87, \"d2v3\": 0.816}}}, \"olmo_temp09\": {\"binary\": {\"acc\": 0.9982, \"ci95\": [0.997, 0.9992], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.7633, \"ci95\": [0.7477, 0.7797], \"auc\": {\"d1v2\": 0.894, \"d2v3\": 0.838}}, \"4class\": {\"acc\": 0.8263, \"ci95\": [0.8147, 0.8385], \"auc\": {\"d0v1\": 0.996, \"d1v2\": 0.903, \"d2v3\": 0.828}}}, \"olmo_topk50\": {\"binary\": {\"acc\": 0.996, \"ci95\": [0.994, 0.9978], \"auc\": {\"d0v1\": 1}}, \"3class\": {\"acc\": 0.661, \"ci95\": [0.644, 0.6773], \"auc\": {\"d1v2\": 0.812, \"d2v3\": 0.739}}, \"4class\": {\"acc\": 0.7435, \"ci95\": [0.73, 0.758], \"auc\": {\"d0v1\": 0.995, \"d1v2\": 0.831, \"d2v3\": 0.738}}}}, \"boundary_dilution\": {\"d2v3_auc_by_granularity_pythia_nuc\": {\"3class\": 0.796, \"4class\": 0.804, \"6class\": 0.689}, \"d1v2_auc_by_granularity_pythia_nuc\": {\"3class\": 0.861, \"4class\": 0.868, \"6class\": 0.83}, \"note\": \"d2v3 AUC drops 14% from 4-class to 6-class (0.804→0.689), confirming decision boundary dilution at higher granularity\"}, \"decoding_strategy_ranking\": {\"4class_acc\": {\"temp09\": 0.814, \"nucleus095\": 0.803, \"topk50\": 0.732}, \"note\": \"topk50 consistently worst across all 3 models; temp09 slightly outperforms nucleus095\"}}, \"conclusion\": \"success\"}, \"zero_shot_llm_baseline_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:41:07.167Z\", \"updated_at\": \"2026-05-15T09:12:23.101Z\", \"hypothesis\": \"Zero-shot LLM baseline: DeepSeek V3.2 直接判断文本递归生成深度 (4-class)，无需统计特征提取。作为 upper-bound baseline 对比 feature-based 方法。\", \"parent\": \"baseline_battery_001\", \"metrics\": {\"four_class_acc\": 0.4, \"n_samples\": 200, \"sample_distribution\": {\"d0\": 56, \"d1\": 47, \"d2\": 49, \"d3\": 48}, \"model\": \"DeepSeek V3.2\", \"method\": \"zero-shot prompting\", \"vs_rf_baseline\": -0.382, \"vs_chance\": 0.15, \"note\": \"40.0% (80/200) above chance (25%) but far below RF 78.2% (-38.2pp). Zero-shot LLM cannot reliably distinguish recursive depth from raw text alone.\"}, \"conclusion\": \"success\", \"notes\": \"DeepSeek V3.2 zero-shot 4-class acc=40.0% (80/200, 样本分布 d0=56/d1=47/d2=49/d3=48)。高于 chance 25% (+15.0pp) 但远低于 RF 78.2% (-38.2pp)。结论：即使最强 LLM 也无法从原始文本可靠判断递归深度——统计特征提取是必要的，这验证了本文 feature-based 方法的价值。[2026-05-15 修正: 原误报 44.3%，经 Reviewer 验证服务器 results 文件确认为 80/200=40.0%]\"}, \"olmo_temp09_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T22:59:50.217Z\", \"updated_at\": \"2026-05-15T06:27:11.061Z\", \"hypothesis\": \"解码策略鲁棒性: OLMo-1B 在 temperature-only τ=0.9 下递归生成的深度信号与 nucleus p=0.95 一致（olmo_temp09_001 重跑，从 Step 3 断点恢复）\", \"parent\": \"olmo_temp09_001\", \"conclusion\": \"killed\", \"notes\": \"Director 确认取消：olmo_temp09_001 数据已完整 (4-class RF 82.03%)，重跑不必要。服务器重启后误分配导致的重复提交。PID 179923 已 force kill，cuda:1 已释放。\"}, \"depth_extension_pythia_d4d5_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T03:56:37.582Z\", \"updated_at\": \"2026-05-15T06:24:41.231Z\", \"hypothesis\": \"Depth extension to d4/d5: EDD 从 d3 (当前 EDD=3 未饱和) 继续延伸——如果 d3v4 和 d4v5 AUC 仍 >0.75，则 EDD≥5，证明递归深度信号至少在 5 代内不饱和\", \"parent\": \"mvp_pipeline_pythia_002\", \"conclusion\": \"success\", \"metrics\": {\"six_class_rf_accuracy\": 0.6232, \"six_class_rf_accuracy_ci\": [0.6113, 0.636], \"six_class_lr_accuracy\": 0.5862, \"pairwise_auc_rf\": {\"d0v1\": 0.9962, \"d1v2\": 0.8231, \"d2v3\": 0.6878, \"d3v4\": 0.6809, \"d4v5\": 0.6948}, \"pairwise_auc_lr\": {\"d0v1\": 0.9908, \"d1v2\": 0.6901, \"d2v3\": 0.6174, \"d3v4\": 0.6828, \"d4v5\": 0.6554}, \"cumulative_auc_rf\": {\"d0v5\": 0.9987, \"d1v5\": 0.9874, \"d2v5\": 0.949, \"d3v5\": 0.8632}, \"edd_at_075\": 2, \"feature_importance_top5\": [\"p90_ppl (0.1376)\", \"var_surprisal (0.1344)\", \"mean_ppl (0.0796)\", \"mean_surprisal (0.0789)\", \"p75_ppl (0.0680)\"], \"finetune_losses\": {\"depth_3\": 0.7634, \"depth_4\": 0.5828}, \"WARNING\": \"6-class pairwise AUC 不可与 4-class 直比，决策边界稀释导致系统性偏低。需 binary pairwise classifier 重新评估。\"}, \"notes\": \"Depth extension d4/d5 完成。6-class RF acc=62.3%（6-class pairwise AUC 因决策边界稀释不可用）。**Binary pairwise 重新评估 (depth_extension_binary_pairwise_002)**: d3v4 AUC=0.784 (>0.75 ✅), d4v5 AUC=0.683 (<0.75 ❌) → **EDD=4**。结论从 negative 修正为 partial success: 深度信号在 d4 仍可区分，d5 饱和。Sanity check: binary d1v2=0.925 vs 4-class 0.861 (+0.064), binary d2v3=0.823 vs 4-class 0.801 (+0.022) — binary 一致高于 4-class，确认决策边界稀释效应存在。\"}, \"depth_extension_binary_pairwise_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:04:35.570Z\", \"updated_at\": \"2026-05-15T06:14:30.023Z\", \"hypothesis\": \"Retry of binary_pairwise_001 (failed due to missing script on server). Dedicated binary RF for d3v4 and d4v5 pairwise AUC. Judgment: d3v4>0.75 + d4v5>0.75 → EDD≥5; d3v4>0.75 only → EDD=4.\", \"parent\": \"depth_extension_binary_pairwise_001\", \"metrics\": {\"d1v2_auc\": 0.925, \"d1v2_ci95\": [0.9138, 0.9354], \"d2v3_auc\": 0.8225, \"d2v3_ci95\": [0.8052, 0.8402], \"d3v4_auc\": 0.7837, \"d3v4_ci95\": [0.7648, 0.8024], \"d4v5_auc\": 0.6832, \"d4v5_ci95\": [0.6611, 0.7045], \"edd_determination\": \"4\"}, \"conclusion\": \"success\", \"notes\": \"Binary pairwise RF (500 trees) on Pythia nucleus d0-d5 (30k samples, 5k/depth). Results: d1v2 AUC=0.9250 (vs 4-class 0.8607, +0.0643), d2v3 AUC=0.8225 (vs 4-class 0.8005, +0.0220), d3v4 AUC=0.7837 [0.7648,0.8024], d4v5 AUC=0.6832 [0.6611,0.7045]. Binary classifiers consistently outperform 4-class pipeline pairwise AUC (as expected, no decision boundary dilution). EDD=4: d3v4 above threshold (0.75) but d4v5 below. Feature extraction for d4/d5 done via Pythia-1.4B frozen model on LoRA-generated text. Top features shift from var_surprisal (d1v2) to p90_ppl/kurtosis (d3v4/d4v5), suggesting tail perplexity becomes the key discriminator at higher depths.\"}, \"depth_extension_binary_pairwise_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T05:22:13.190Z\", \"updated_at\": \"2026-05-15T06:02:34.878Z\", \"hypothesis\": \"Dedicated binary pairwise RF 评估 d3v4 和 d4v5 可区分性。6-class RF 的 pairwise AUC 因决策边界稀释不可靠（d2v3 从 4-class 0.80 降到 0.69 是 artifact）。Binary classifier 消除此 artifact，与原 4-class pipeline 的 d0v1/d1v2/d2v3 AUC 可比。判定标准：binary d3v4 AUC > 0.75 且 d4v5 AUC > 0.75 → EDD≥5；d3v4 > 0.75 但 d4v5 < 0.75 → EDD=4。\", \"parent\": \"depth_extension_pythia_d4d5_001\", \"conclusion\": \"failed\"}, \"dcol_roberta_v6_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T04:20:40.271Z\", \"updated_at\": \"2026-05-15T05:59:47.351Z\", \"hypothesis\": \"DCOL v6: RoBERTa-large 替代 DeBERTa 解决数值不稳定。lr=5e-5 + grad clip 1.0 + NaN guard + collapse guard (step 500 acc&lt;30% kill)。若 4-class acc > RF baseline (78.2%) 则 DCOL 成功，否则降级为 negative result。\", \"parent\": \"dcol_deberta_005\", \"conclusion\": \"negative\", \"metrics\": {\"test_acc\": 0.6448, \"test_mae\": 0.4052, \"best_val_acc\": 0.6436, \"best_epoch\": 1, \"epochs_run\": 4, \"early_stopping\": true, \"train_acc_final\": 0.75, \"rf_baseline\": 0.782, \"delta_vs_baseline\": -0.137, \"overfitting\": \"severe (train 75% vs val 64.4% at best epoch)\", \"stability\": \"resolved (no NaN, no collapse, collapse guard passed at step 500)\"}, \"notes\": \"DCOL v6 (RoBERTa-large) 正常完成，解决了 DeBERTa 数值稳定性问题（无 NaN/collapse）。但 test acc=64.5% 远低于 RF baseline 78.2% (-13.7pp)。严重过拟合：train acc 60→75%，val acc epoch 1 后持续下降。Early stopping 在 epoch 4 触发。DCOL v1-v6 全部失败：v1-v5 DeBERTa 数值崩溃，v6 RoBERTa 稳定但准确率不足。结论：DCOL contrastive ordinal loss 对此 4-class depth estimation 任务表达能力不足。符合 D011 framing（DCOL 降级为 negative analysis section）。Checkpoint: /root/autodl-tmp/recursive_gen_depth_est/checkpoints/dcol_roberta_v6/best_model.pt\"}, \"cross_strategy_loo_zscore_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T05:11:42.230Z\", \"updated_at\": \"2026-05-15T05:12:33.614Z\", \"parent\": \"cross_strategy_loo_001\", \"hypothesis\": \"Z-score standardization recovers temp09 d1v2 AUC from covariate shift inversion in cross-strategy LOO (RF classifier)\", \"metrics\": {\"mean_raw_acc\": 0.5908, \"mean_zscore_acc\": 0.5915, \"raw\": {\"pythia_holdout_nucleus\": {\"acc\": 0.6935, \"d1v2_auc\": 0.6903, \"d2v3_auc\": 0.7626}, \"pythia_holdout_temp09\": {\"acc\": 0.6281, \"d1v2_auc\": 0.576, \"d2v3_auc\": 0.724}, \"pythia_holdout_topk50\": {\"acc\": 0.5151, \"d1v2_auc\": 0.6393, \"d2v3_auc\": 0.5801}, \"gpt2xl_holdout_nucleus\": {\"acc\": 0.5993, \"d1v2_auc\": 0.7826, \"d2v3_auc\": 0.4985}, \"gpt2xl_holdout_temp09\": {\"acc\": 0.5609, \"d1v2_auc\": 0.1288, \"d2v3_auc\": 0.6366}, \"gpt2xl_holdout_topk50\": {\"acc\": 0.5364, \"d1v2_auc\": 0.8308, \"d2v3_auc\": 0.7222}, \"olmo_holdout_nucleus\": {\"acc\": 0.6538, \"d1v2_auc\": 0.7931, \"d2v3_auc\": 0.6076}, \"olmo_holdout_temp09\": {\"acc\": 0.5816, \"d1v2_auc\": 0.2529, \"d2v3_auc\": 0.7015}, \"olmo_holdout_topk50\": {\"acc\": 0.5488, \"d1v2_auc\": 0.8549, \"d2v3_auc\": 0.7107}}, \"zscore\": {\"pythia_holdout_nucleus\": {\"acc\": 0.6992, \"d1v2_auc\": 0.7043, \"d2v3_auc\": 0.7683}, \"pythia_holdout_temp09\": {\"acc\": 0.6368, \"d1v2_auc\": 0.5943, \"d2v3_auc\": 0.7352}, \"pythia_holdout_topk50\": {\"acc\": 0.5155, \"d1v2_auc\": 0.6386, \"d2v3_auc\": 0.5804}, \"gpt2xl_holdout_nucleus\": {\"acc\": 0.5959, \"d1v2_auc\": 0.788, \"d2v3_auc\": 0.4927}, \"gpt2xl_holdout_temp09\": {\"acc\": 0.5632, \"d1v2_auc\": 0.1348, \"d2v3_auc\": 0.631}, \"gpt2xl_holdout_topk50\": {\"acc\": 0.5356, \"d1v2_auc\": 0.8391, \"d2v3_auc\": 0.7282}, \"olmo_holdout_nucleus\": {\"acc\": 0.6506, \"d1v2_auc\": 0.796, \"d2v3_auc\": 0.6078}, \"olmo_holdout_temp09\": {\"acc\": 0.5782, \"d1v2_auc\": 0.2497, \"d2v3_auc\": 0.6871}, \"olmo_holdout_topk50\": {\"acc\": 0.5484, \"d1v2_auc\": 0.8579, \"d2v3_auc\": 0.7056}}, \"temp09_d1v2_delta\": {\"pythia\": 0.0183, \"gpt2xl\": 0.006, \"olmo\": -0.0033}, \"finding\": \"Z-score does NOT fix temp09 d1v2 inversion in RF — RF is scale-invariant (tree splits unaffected by monotonic transforms). Prior z-score recovery (0.13→0.68) was with LR, not RF.\"}, \"conclusion\": \"negative\", \"notes\": \"Z-score standardization has negligible effect on RF cross-strategy LOO. temp09 d1v2 AUC remains inverted: GPT-2 XL 0.1288→0.1348, OLMo 0.2529→0.2497, Pythia 0.576→0.594. Root cause: RF is a tree-based model invariant to monotonic feature transforms — z-score shifts/scales features but preserves relative ordering, so split thresholds adapt automatically. Prior independent verification (GPT-2 XL 0.13→0.68, OLMo 0.25→0.83) was with a scale-sensitive classifier (LR), not RF. Raw results match cross_strategy_loo_001 exactly (mean acc=0.5908). Non-temp09 impact negligible (mean Δd1v2=+0.006). Conclusion: covariate shift hypothesis is correct but the z-score fix is classifier-dependent — works for LR, not for RF.\"}, \"cross_model_loo_v1\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T04:08:20.440Z\", \"updated_at\": \"2026-05-15T05:11:31.448Z\", \"conclusion\": \"success\", \"metrics\": {\"mean_acc\": 0.664, \"mean_3class_acc\": 0.5544, \"holdout_pythia\": {\"acc\": 0.6242, \"ci95\": [0.6205, 0.6282], \"3class_acc\": 0.499, \"3class_ci95\": [0.4944, 0.5034], \"d1v2_auc\": 0.5617, \"d1v3_auc\": 0.8547, \"d2v3_auc\": 0.6534, \"d0v1_auc\": 0.9921, \"d0v2_auc\": 0.9999, \"d0v3_auc\": 0.9998, \"per_class\": {\"d0\": {\"P\": 0.9889, \"R\": 1, \"F1\": 0.9944}, \"d1\": {\"P\": 0.6655, \"R\": 0.493, \"F1\": 0.5664}, \"d2\": {\"P\": 0.3699, \"R\": 0.2677, \"F1\": 0.3106}, \"d3\": {\"P\": 0.483, \"R\": 0.7363, \"F1\": 0.5834}}}, \"holdout_olmo\": {\"acc\": 0.6921, \"ci95\": [0.6884, 0.696], \"3class_acc\": 0.592, \"3class_ci95\": [0.5873, 0.5965], \"d1v2_auc\": 0.7687, \"d1v3_auc\": 0.9277, \"d2v3_auc\": 0.6862, \"per_class\": {\"d0\": {\"P\": 0.9783, \"R\": 0.9925, \"F1\": 0.9854}, \"d1\": {\"P\": 0.7111, \"R\": 0.7549, \"F1\": 0.7324}, \"d2\": {\"P\": 0.4616, \"R\": 0.4327, \"F1\": 0.4467}, \"d3\": {\"P\": 0.5964, \"R\": 0.5883, \"F1\": 0.5923}}}, \"holdout_gpt2xl\": {\"acc\": 0.6756, \"ci95\": [0.6717, 0.6795], \"3class_acc\": 0.5723, \"3class_ci95\": [0.5679, 0.5767], \"d1v2_auc\": 0.8157, \"d1v3_auc\": 0.9149, \"d2v3_auc\": 0.6639, \"d0v1_auc\": 0.9927, \"d0v2_auc\": 0.9919, \"d0v3_auc\": 0.9876, \"per_class\": {\"d0\": {\"P\": 0.9484, \"R\": 0.9853, \"F1\": 0.9665}, \"d1\": {\"P\": 0.7093, \"R\": 0.7465, \"F1\": 0.7274}, \"d2\": {\"P\": 0.4521, \"R\": 0.5255, \"F1\": 0.486}, \"d3\": {\"P\": 0.5963, \"R\": 0.445, \"F1\": 0.5097}}}, \"mean_per_class_recall\": {\"d0\": 0.9926, \"d1\": 0.6648, \"d2\": 0.4086, \"d3\": 0.5899}, \"lowest_recall_class\": \"d2\", \"lowest_recall_value\": 0.4086, \"detailed_artifact\": \"cross_model_loo_detailed.json\"}}, \"baseline_battery_9cell_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T04:26:41.388Z\", \"updated_at\": \"2026-05-15T05:11:25.784Z\", \"hypothesis\": \"9-cell baseline battery: 4 种分类方法 (RF/LR/CORAL/DivEye) 在 3×3 矩阵全部 cells 上的 4-class accuracy 对比，生成 paper Table 1\", \"parent\": \"baseline_battery_001\", \"conclusion\": \"success\", \"metrics\": {\"best_acc_matrix\": {\"pythia_nucleus\": 0.782, \"pythia_temp09\": 0.772, \"pythia_topk50\": 0.688, \"olmo_nucleus\": 0.796, \"olmo_temp09\": 0.827, \"olmo_topk50\": 0.759, \"gpt2xl_nucleus\": 0.843, \"gpt2xl_temp09\": 0.853, \"gpt2xl_topk50\": 0.754}, \"methods\": [\"RF\", \"LR\", \"CORAL\", \"DivEye\"], \"cells\": 9, \"finding\": \"RF ≈ CORAL > DivEye > LR, max gap ~4pp. GPT-2 XL temp09 best (85.3%), model effect > strategy effect\", \"WARNING\": \"best_acc_matrix stores best-across-ALL-methods accuracy, NOT RF-only. For RF accuracy use each cell's own registry (e.g. olmo_topk50_001.metrics.four_class.rf_accuracy). olmo_topk50 diff=2.2pp, olmo_nucleus diff=0.83pp.\"}, \"notes\": \"9-cell baseline battery 完成。⚠️ 字段命名问题：`best_acc_matrix_rf` 实际存储的是所有方法（RF/LR/CORAL/DivEye）中的最优 accuracy，不是纯 RF accuracy。影响 olmo_topk50：此字段记 0.759（实为 LR），RF 实际为 0.737，差 2.2pp。论文引用 RF accuracy 时必须用各 cell 独立 registry（如 olmo_topk50_001.metrics.four_class.rf_accuracy = 0.742），不要用此字段。其余 8 cells RF 恰好是最优方法，所以值一致。Reconciliation check 2026-05-15 确认：pipeline↔edd_sensitivity AUC 27/27 一致，pipeline↔registry AUC 41/41 一致，EDD 值一致。\"}, \"olmo_topk50_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T22:30:51.656Z\", \"updated_at\": \"2026-05-15T04:55:10.850Z\", \"hypothesis\": \"解码策略鲁棒性: OLMo-1B 在 top-k k=50 下递归生成的深度信号与 nucleus p=0.95 一致，支持跨策略泛化\", \"parent\": \"cross_model_olmo_002\", \"notes\": \"OLMo-1B top-k k=50 完成，conclusion=success。4-class LR 75.7% / RF 74.2%，d1v2 AUC LR 0.829 / RF 0.831。3-class filtered LR 67.0% / RF 67.0%。\\n\\nvs baseline 对比（4-class LR acc / d1v2 AUC LR）：\\n| Config         | 4-class LR | d1v2 AUC |\\n|----------------|-----------|----------|\\n| OLMo temp09    | 82.03%    | 0.901    |\\n| OLMo nucleus   | 78.8%     | 0.867    |\\n| OLMo topk50    | 75.7%     | 0.829    |\\n| Pythia topk50  | 69.6%     | 0.752    |\\n\\nOLMo topk50 比 OLMo nucleus 低 ~3pp，比 Pythia topk50 高 ~6pp。Top-k 解码略微降低深度可区分性（vs nucleus），但 OLMo 仍显著优于 Pythia，确认模型效应 > 解码策略效应。3×3 矩阵最后一格完成。\\n\\n**[mean_ppl outlier 分析 2026-05-15]**: 1 个极端样本 (sample_id=6923, mean_ppl=1.43e13) 贡献了 depth-1 mean_ppl 总和的 94.4%。Token-level perplexity 极度重尾 (kurtosis>4900, CV=67×)。mean_ppl 即使剔除 >1e6 仍非单调。p90_ppl 完美单调 (566.8→143.0→91.7→73.1, CV 0.28-0.67)。结论：percentile-based features (p90_ppl) 统计鲁棒性远优于 mean-based (mean_ppl)，这是 Atlas 选择 p90_ppl 为核心特征的统计学依据。详见 artifacts/olmo_topk50_mean_ppl_outlier_analysis.md。\", \"metrics\": {\"four_class\": {\"lr_accuracy\": 0.757, \"lr_accuracy_ci\": [0.7425, 0.7702], \"rf_accuracy\": 0.742, \"rf_accuracy_ci\": [0.7282, 0.7555]}, \"pairwise_auc\": {\"lr\": {\"d0v1\": 0.9969, \"d0v2\": 0.9995, \"d0v3\": 0.9998, \"d1v2\": 0.8293, \"d1v3\": 0.9592, \"d2v3\": 0.7497}, \"rf\": {\"d0v1\": 0.993, \"d0v2\": 0.9983, \"d0v3\": 0.9991, \"d1v2\": 0.8305, \"d1v3\": 0.9591, \"d2v3\": 0.7357}}, \"three_class\": {\"lr_accuracy\": 0.6567, \"lr_accuracy_ci\": [0.6403, 0.6733], \"rf_accuracy\": 0.6517, \"rf_accuracy_ci\": [0.635, 0.6687]}, \"three_class_filtered\": {\"lr_accuracy\": 0.6703, \"lr_accuracy_ci\": [0.653, 0.6882], \"rf_accuracy\": 0.6699, \"rf_accuracy_ci\": [0.6537, 0.6875]}, \"three_class_filtered_auc\": {\"lr\": {\"d1v2\": 0.7903, \"d1v3\": 0.97, \"d2v3\": 0.7501}, \"rf\": {\"d1v2\": 0.8071, \"d1v3\": 0.9645, \"d2v3\": 0.7364}}, \"feature_importance_top5\": [\"p90_ppl\", \"var_surprisal\", \"p75_ppl\", \"mean_surprisal\", \"p25_ppl\"], \"finetune_loss\": {\"depth_1\": 1.946, \"depth_2\": 1.726}, \"code_contamination\": {\"narrow_pct\": {\"depth_0\": 0.4, \"depth_1\": 0.8, \"depth_2\": 0.3, \"depth_3\": 0.4}, \"broad_pct\": {\"depth_0\": 0.5, \"depth_1\": 2.5, \"depth_2\": 0.8, \"depth_3\": 0.7}}}, \"conclusion\": \"success\"}, \"atlas_v2_analysis\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T04:12:09.137Z\", \"updated_at\": \"2026-05-15T04:24:05.713Z\", \"hypothesis\": \"Atlas v2 (9-cell): p90_ppl 和 var_surprisal 在所有 9 cells 中稳定为 top-2 features，EDD≥3 在多数 cells 成立，证明深度退化信号具有跨模型跨策略一致性\", \"parent\": \"atlas_v1_analysis\", \"conclusion\": \"success\", \"metrics\": {\"p90_ppl_in_top2\": \"9/9\", \"var_surprisal_in_top2\": \"7/9\", \"edd_equals_3_at_T075\": \"7/9\", \"edd_distribution_T075\": {\"2\": 2, \"3\": 7}, \"cross_model_rank_corr_range\": \"[0.619, 0.954]\", \"cross_model_rank_corr_mean\": 0.868, \"cv5_accuracy_range\": \"[0.688, 0.859]\", \"cells_covered\": \"9/9\"}}, \"cross_model_loo_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T04:01:46.616Z\", \"updated_at\": \"2026-05-15T04:16:09.538Z\", \"hypothesis\": \"Cross-model LOO: 深度信号跨模型泛化，train on 2 families test on 3rd 的 4-class acc ≥ 45%（plan_005 gate）\", \"conclusion\": \"killed\", \"metrics\": {\"mean_4class_acc\": 0.664, \"holdout_pythia\": {\"acc\": 0.6242, \"ci\": [0.6206, 0.6282], \"d1v2_auc\": 0.5617, \"d2v3_auc\": 0.6534}, \"holdout_olmo\": {\"acc\": 0.6921, \"ci\": [0.6886, 0.6959], \"d1v2_auc\": 0.7687, \"d2v3_auc\": 0.6862}, \"holdout_gpt2xl\": {\"acc\": 0.6756, \"ci\": [0.6719, 0.6792], \"d1v2_auc\": 0.8157, \"d2v3_auc\": 0.6639}, \"per_class_recall\": {\"holdout_pythia\": {\"d0\": 1, \"d1\": 0.493, \"d2\": 0.268, \"d3\": 0.736}, \"holdout_olmo\": {\"d0\": 0.993, \"d1\": 0.755, \"d2\": 0.433, \"d3\": 0.588}, \"holdout_gpt2xl\": {\"d0\": 0.985, \"d1\": 0.747, \"d2\": 0.526, \"d3\": 0.445}}, \"gate_passed\": true, \"gate_threshold\": 0.45}, \"notes\": \"CANCELLED: 被 cross_model_loo_v1 替代。此条目为 orphaned PREPARING entry，已标记废弃。\"}, \"batch_feature_extraction_5cells\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T03:11:55.553Z\", \"updated_at\": \"2026-05-15T03:53:53.596Z\", \"conclusion\": \"success\"}, \"gpt2xl_topk50_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T22:30:51.976Z\", \"updated_at\": \"2026-05-15T03:51:07.924Z\", \"hypothesis\": \"解码策略鲁棒性: GPT-2 XL 在 top-k k=50 下递归生成的深度信号与 nucleus p=0.95 一致，支持跨策略泛化\", \"parent\": \"cross_model_gpt2xl_001\", \"conclusion\": \"success\", \"metrics\": {\"four_class\": {\"accuracy\": 0.766, \"depth1_vs_depth2_auc\": 0.8259, \"pass\": true}, \"three_class\": {\"accuracy\": 0.695, \"depth1_vs_depth2_auc\": 0.8392, \"pass\": true}, \"three_class_filtered\": {\"accuracy\": 0.684, \"depth1_vs_depth2_auc\": 0.8314, \"pass\": true}}, \"notes\": \"GPT-2 XL top-k k=50 完成（3×3 矩阵第 9 格）。evaluator=GPT-2 XL。\\n\\n重提取后核心指标 (2026-05-15 reextract): RF 76.59% [75.20-77.93%], LR 71.3%, d1v2 AUC RF 0.826 / LR 0.781。3-class RF 69.47%, 3-class filtered RF 68.36%。Code contamination 极低 (narrow ≤1.6%)。\\n\\nvs 同模型不同解码策略:\\n| Config     | RF 4-class | d1v2 AUC | 3-class RF |\\n|------------|-----------|----------|------------|\\n| temp09     | 85.4%     | 0.937    | 82.0%      |\\n| nucleus    | 83.3%     | 0.913    | 79.3%      |\\n| topk50     | 76.6%     | 0.826    | 69.5%      |\\n\\nTop-k 使 GPT-2 XL 深度信号下降 -6.7pp (vs nucleus), -8.8pp (vs temp09)。Feature importance top-5: p90_ppl, p75_ppl, mean_surprisal, var_surprisal, p50_ppl。\"}, \"dcol_deberta_005\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T02:47:32.444Z\", \"updated_at\": \"2026-05-15T03:46:41.040Z\", \"hypothesis\": \"DCOL v5 (LoRA r=16 alpha=16, margin_lr=1e-4): DeBERTa-v3-large + LoRA + Contrastive Ordinal Loss，修正 margin_lr 从 1e-3 到 1e-4 避免 embedding collapse\", \"parent\": \"dcol_deberta_004\", \"notes\": \"DCOL v5: LoRA (r=16, alpha=16) + margin_lr=1e-4。Killed: loss=NaN 3000+ steps, GPU 1 空转。Reviewer 确认 PID 283196 仍在空转。tmux session + 所有子进程已强制终止。DCOL 连续 5 次失败 (v1 embedding collapse, v2 OOM zombie, v3 killed, v4 margin_lr violation, v5 NaN)。\", \"conclusion\": \"failed\"}, \"dcol_deberta_004\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T02:41:50.066Z\", \"updated_at\": \"2026-05-15T02:48:09.179Z\", \"hypothesis\": \"DCOL v4 (LoRA r=16 alpha=16): DeBERTa-v3-large + LoRA + Contrastive Ordinal Loss，冻结 backbone 只训 LoRA adapter + head + margins\", \"parent\": \"dcol_deberta_003\", \"notes\": \"DCOL v4 killed: margin_lr=1e-3 违反硬约束(≤1e-4)。v1 已因 1e-3 导致 embedding collapse。LoRA 不改变此风险。Director 指令以 margin_lr=1e-4 重跑为 dcol_deberta_005。\", \"conclusion\": \"killed\"}, \"dcol_deberta_003\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T22:45:36.720Z\", \"updated_at\": \"2026-05-15T02:22:18.204Z\", \"notes\": \"DCOL v3 killed: 全参微调导致训练崩溃 (step 340 acc 40.8%→32.0%)。Director 诊断: full fine-tuning 破坏 DeBERTa 预训练表示。方案: 转 LoRA 微调 (dcol_deberta_004)。PID 241769 + 262897 已终止。\", \"conclusion\": \"killed\"}, \"olmo_temp09_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T20:34:19.885Z\", \"updated_at\": \"2026-05-15T00:10:12.526Z\", \"hypothesis\": \"解码策略鲁棒性: OLMo-1B 在 temperature-only τ=0.9 下递归生成的深度信号与 nucleus p=0.95 一致，支持跨策略泛化\", \"parent\": \"cross_model_olmo_002\", \"notes\": \"OLMo temp09 是目前最强配置: 4-class RF 82.03% (OLMo nucleus 78.8% +3.26pp, Pythia temp09 76.3% +5.78pp)。d1v2 AUC 0.901。3-class filtered RF 77.57%。Code contamination 极低 (narrow ≤0.7%)。关键特征: p90_ppl, var_surprisal, p75_ppl。与 GPT-2 XL 不同，OLMo 的 temp09 也优于 nucleus，进一步证明解码策略对信号强度的影响是模型依赖的。\", \"metrics\": {\"four_class\": {\"rf_accuracy\": 0.8203, \"d1v2_auc\": 0.901}, \"three_class_filtered\": {\"rf_accuracy\": 0.7757}, \"finetune_losses\": {\"depth_0\": 2.27, \"depth_1\": 1.63, \"depth_2\": 1.18}, \"code_contamination_narrow_max\": 0.007, \"top_features\": [\"p90_ppl (0.199)\", \"var_surprisal (0.174)\", \"p75_ppl (0.126)\"]}, \"conclusion\": \"success\"}, \"baseline_battery_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T23:25:45.021Z\", \"updated_at\": \"2026-05-14T23:26:06.409Z\", \"conclusion\": \"success\", \"metrics\": {\"ppl_reg_single_4class_acc\": 0.251, \"ppl_reg_multi_4class_acc\": 0.622, \"ce_mlp_4class_acc\": 0.749, \"coral_4class_acc\": 0.7807, \"coral_3class_acc\": 0.7089, \"coral_mae\": 0.2273, \"coral_d1v2_auc\": 0.8179, \"diveye_4class_acc\": 0.7817, \"diveye_3class_acc\": 0.7098, \"diveye_d1v2_auc\": 0.8654, \"rf_4class_acc\": 0.781, \"lr_4class_acc\": 0.75, \"note\": \"CE-MLP 74.9% may be undertrained (5 epochs); CORAL updated to 100 epochs. All results from Pythia nucleus baseline features.\"}, \"notes\": \"Baseline battery (plan_009) 完成。6 种 feature-based baselines 在 Pythia nucleus 的 features_all.jsonl 上测试。CORAL 修复后从 53.7%→78.1% (epochs 5→100)。DivEye(XGBoost) 78.2%。CE-MLP 74.9%（可能训练不足，待用默认参数确认）。Zero-shot LLM baseline 代码就绪但需 API key。所有 baseline 均低于 GPT-2 XL temp09 的 85.4%。\"}, \"atlas_v1_analysis\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T22:56:33.920Z\", \"updated_at\": \"2026-05-14T22:57:02.614Z\", \"hypothesis\": \"Depth Degradation Atlas v1: 跨模型/策略的深度退化特征具有单调性(monotonicity)，EDD 可量化退化饱和点\", \"conclusion\": \"success\", \"metrics\": {\"monotonicity_rho_range\": [-0.89, -0.82], \"edd\": 3, \"edd_saturated\": false, \"cross_model_jaccard\": 0.667, \"cross_model_rank_corr\": 0.85, \"artifacts\": [\"monotonicity_scores.json\", \"cross_model_comparison.json\", \"edd_analysis.json\", \"feature_trajectory.json\"]}}, \"dcol_deberta_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T22:38:54.868Z\", \"updated_at\": \"2026-05-14T22:49:16.515Z\", \"hypothesis\": \"DCOL v2 (修复 embedding collapse): margin_lr=1e-4, L2 norm, cl_weight=1.0\", \"parent\": \"dcol_deberta_001\", \"conclusion\": \"failed\", \"notes\": \"OOM 根因确认：dcol_deberta_002 (57GB) 与 gpt2xl_temp09 extract_features (9GB) 同时占用 GPU 0 导致显存竞争。非代码 bug，非僵尸残留——PID 193689 就是 dcol_002 本身。GPU 0 现已完全清空 (0MiB/97887MiB)。代码 dcol_trainer.py 和数据 features_all.jsonl 均完好。v3 可安全重试。\"}, \"gpt2xl_temp09_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T18:28:04.139Z\", \"updated_at\": \"2026-05-14T22:43:57.362Z\", \"hypothesis\": \"解码策略鲁棒性: GPT-2 XL 在 temperature-only τ=0.9 下递归生成的深度信号与 nucleus p=0.95 一致，支持跨策略泛化\", \"parent\": \"cross_model_gpt2xl_001\", \"metrics\": {\"data\": {\"samples_per_depth\": 5000, \"total_samples\": 20000, \"depths\": 4}, \"finetune_losses\": {\"depth_1\": 2.5498, \"depth_2\": 1.6972, \"depth_3\": 1.2922}, \"code_contamination\": {\"depth_0\": {\"broad\": 25, \"narrow\": 20, \"broad_pct\": 0.5, \"narrow_pct\": 0.4}, \"depth_1\": {\"broad\": 25, \"narrow\": 40, \"broad_pct\": 0.5, \"narrow_pct\": 0.8}, \"depth_2\": {\"broad\": 34, \"narrow\": 80, \"broad_pct\": 0.7, \"narrow_pct\": 1.6}, \"depth_3\": {\"broad\": 25, \"narrow\": 76, \"broad_pct\": 0.5, \"narrow_pct\": 1.5}}, \"four_class\": {\"rf_accuracy\": 0.8542, \"rf_accuracy_ci\": [0.843, 0.8653], \"lr_accuracy\": 0.8155, \"lr_accuracy_ci\": [0.8025, 0.8273], \"rf_auc\": {\"d0v1\": 0.9963, \"d0v2\": 0.9992, \"d0v3\": 1, \"d1v2\": 0.9367, \"d1v3\": 0.9947, \"d2v3\": 0.8815}, \"lr_auc\": {\"d0v1\": 0.984, \"d0v2\": 0.9998, \"d0v3\": 1, \"d1v2\": 0.8903, \"d1v3\": 0.9824, \"d2v3\": 0.8183}, \"top_features\": [\"p90_ppl\", \"mean_surprisal\", \"p75_ppl\", \"var_surprisal\"]}, \"three_class\": {\"rf_accuracy\": 0.82, \"rf_accuracy_ci\": [0.806, 0.834], \"lr_accuracy\": 0.7773, \"lr_accuracy_ci\": [0.7627, 0.792], \"rf_auc\": {\"d1v2\": 0.9418, \"d1v3\": 0.9967, \"d2v3\": 0.8849}}, \"three_class_filtered\": {\"rf_accuracy\": 0.815, \"rf_accuracy_ci\": [0.7999, 0.8298], \"lr_accuracy\": 0.7869, \"lr_accuracy_ci\": [0.7711, 0.8016], \"rf_auc\": {\"d1v2\": 0.937, \"d1v3\": 0.9944, \"d2v3\": 0.8891}}}, \"conclusion\": \"success\", \"notes\": \"GPT-2 XL temp09 意外优于 nucleus baseline: 4-class RF 85.42% vs 83.3% (+2.1pp), 3-class 82.0% vs 79.3% (+2.7pp)。与 Pythia 方向相反（Pythia temp09 降 1.9pp）。解码策略对深度信号的影响是模型依赖的。d2v3 AUC 基本持平（0.8815 vs 0.883），d1v2 AUC 提升（0.9367 vs 0.913）。filtered 3-class 81.5% 与 unfiltered 82.0% 接近，code contamination 影响小。\"}, \"dcol_deberta_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T19:27:49.873Z\", \"updated_at\": \"2026-05-14T22:35:52.089Z\", \"hypothesis\": \"DCOL (DeBERTa-v3-large + Contrastive Ordinal Loss with learnable margins) 从原始文本直接预测递归生成深度，优于统计特征+RF方法\", \"conclusion\": \"failed\", \"notes\": \"Embedding collapse: margin_lr=1e-3 太高（与 base lr 2e-5 差 50x），导致 margins 过快收缩。CL loss 从 0.46 塌缩到 0.03，但 4-class acc 仅 31.5%（Epoch 6）。训练无意义，已 kill。修复方案：margin_lr→1e-4, 添加 L2 norm, cl_weight→1.0。\"}, \"cross_model_olmo_temp09_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T20:34:13.042Z\", \"updated_at\": \"2026-05-14T20:37:44.308Z\", \"hypothesis\": \"OLMo-1B cross-model validation with temp_only decoding (t=0.9)\", \"parent\": \"plan_002b\", \"conclusion\": \"killed\", \"notes\": \"重复条目，已清理。保留 olmo_temp09_001 作为正式条目。\"}, \"pythia_topk50_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T14:49:28.112Z\", \"updated_at\": \"2026-05-14T20:32:54.105Z\", \"hypothesis\": \"解码策略鲁棒性: Pythia-1.4B 在 top-k k=50 下递归生成的深度信号与 nucleus p=0.95 一致，支持跨策略泛化\", \"conclusion\": \"success\", \"metrics\": {\"rf_4class_acc\": 0.696, \"rf_4class_acc_ci\": [0.6825, 0.7107], \"lr_4class_acc\": 0.682, \"rf_3class_acc\": 0.592, \"rf_3class_acc_ci\": [0.575, 0.6107], \"rf_3class_filtered_acc\": 0.6133, \"rf_3class_filtered_acc_ci\": [0.593, 0.6312], \"pairwise_auc_rf\": {\"d0v1\": 0.9927, \"d0v2\": 0.9983, \"d0v3\": 0.9978, \"d1v2\": 0.7518, \"d1v3\": 0.9176, \"d2v3\": 0.6918}, \"pairwise_auc_3class_filtered_rf\": {\"d1v2\": 0.768, \"d1v3\": 0.9323, \"d2v3\": 0.7013}, \"feature_importance_top5\": [\"var_surprisal\", \"p90_ppl\", \"mean_ppl\", \"mean_surprisal\", \"p75_ppl\"], \"finetune_loss\": {\"depth_0\": 2.2406, \"depth_1\": 1.6704, \"depth_2\": 1.4374}, \"code_contamination_narrow\": {\"depth_0\": 0.004, \"depth_1\": 0.077, \"depth_2\": 0.123, \"depth_3\": 0.131}}, \"notes\": \"## pythia_topk50_001 分析结果\\n\\n### 核心指标\\n- RF 4-class acc: 69.6% (chance 25%), PASS\\n- RF 3-class acc: 59.2% (chance 33.3%)\\n- RF 3-class filtered acc: 61.3%\\n- d1v2 AUC: 0.7518, d2v3 AUC: 0.6918\\n\\n### vs Baseline (nucleus p=0.95) 对比\\n| Metric | topk50 | baseline | delta |\\n|--------|--------|----------|-------|\\n| 4-class acc | 69.6% | 78.2% | -8.6pp |\\n| 3-class acc | 59.2% | 70.8% | -11.6pp |\\n| d0v1 AUC | 0.9927 | 0.9975 | -0.005 |\\n| d1v2 AUC | 0.7518 | 0.8607 | -0.109 |\\n| d2v3 AUC | 0.6918 | 0.8005 | -0.109 |\\n\\n### vs temp09 对比\\n| Metric | topk50 | temp09 | delta |\\n|--------|--------|--------|-------|\\n| 4-class acc | 69.6% | 76.25% | -6.65pp |\\n| 3-class acc | 59.2% | 69.83% | -10.6pp |\\n| d1v2 AUC | 0.7518 | 0.8327 | -0.081 |\\n| d2v3 AUC | 0.6918 | 0.7928 | -0.101 |\\n\\n### Feature importance 一致性\\nTop-5 与 baseline 完全一致: var_surprisal, p90_ppl, mean_ppl, mean_surprisal, p75_ppl\\n\\n### Code contamination (narrow)\\nd0=0.4%, d1=7.7%, d2=12.3%, d3=13.1%（高于 baseline，top-k 产生更多 code-like text）\\nFiltered 3-class 性能反而略高于 unfiltered (61.3% vs 59.2%)，说明 code contamination 不是性能的主要驱动\\n\\n### 结论\\nSUCCESS — 深度信号在 top-k 采样下仍然存在（69.6% >> 25% chance），但信号强度显著低于 nucleus (-8.6pp) 和 temp09 (-6.65pp)。\\n跨策略泛化成立（信号存在），但不同采样策略对信号强度有影响。Top-k 的截断式采样比连续概率重分配（nucleus/temperature）保留的深度信号更弱。\"}, \"cross_model_gpt2xl_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T14:10:51.209Z\", \"updated_at\": \"2026-05-14T18:48:19.037Z\", \"metrics\": {\"four_class_acc_rf\": 0.833, \"four_class_acc_ci\": [0.823, 0.845], \"four_class_acc_lr\": 0.813, \"auc_0v1\": 0.9941, \"auc_0v2\": 0.9965, \"auc_0v3\": 0.9988, \"auc_1v2\": 0.9131, \"auc_1v3\": 0.9857, \"auc_2v3\": 0.8829, \"three_class_acc\": 0.793, \"three_class_acc_ci\": [0.778, 0.806], \"three_class_auc_1v2\": 0.9109, \"three_class_auc_1v3\": 0.989, \"three_class_auc_2v3\": 0.8885, \"finetune_losses\": {\"depth_0\": 2.55, \"depth_1\": 1.715, \"depth_2\": 1.342}, \"top_features\": [\"p90_ppl (0.208)\", \"var_surprisal (0.208)\", \"p75_ppl (0.103)\", \"mean_surprisal (0.082)\", \"mean_ppl (0.065)\"], \"code_contamination\": {\"d0\": 0.005, \"d1\": 0.005, \"d2\": 0.013, \"d3\": 0.007}}, \"notes\": \"Pipeline 完成 (3x finetune + 3x generate + feature extraction + 4-class/3-class classification + code contamination)。4 个 depth 各 5000 样本。Loss 递减正常: 2.55→1.715→1.342。结果文件: results/gpt2xl/ (classification_report.txt, pairwise_auc.json, feature_importance.json, three_class_*)。\", \"conclusion\": \"success\"}, \"cross_model_olmo_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T14:52:05.783Z\", \"updated_at\": \"2026-05-14T18:32:00.366Z\", \"hypothesis\": \"跨模型泛化: OLMo-1B 递归生成的统计特征与 Pythia-1.4B 一致，支持深度估计跨模型迁移 (重跑 olmo_001, 修复脚本 bug)\", \"parent\": \"cross_model_olmo_001\", \"conclusion\": \"success\", \"metrics\": {\"four_class_acc_rf\": 0.788, \"four_class_acc_ci\": [0.776, 0.8], \"four_class_acc_lr\": 0.751, \"auc_0v1\": 0.9834, \"auc_0v2\": 0.9949, \"auc_0v3\": 0.9989, \"auc_1v2\": 0.8673, \"auc_1v3\": 0.9806, \"auc_2v3\": 0.8124, \"three_class_acc\": 0.744, \"three_class_acc_ci\": [0.728, 0.76], \"three_class_mae\": 0.27, \"three_class_auc_1v2\": 0.8664, \"three_class_auc_1v3\": 0.9852, \"three_class_auc_2v3\": 0.8274, \"three_class_recall\": {\"d1\": 0.864, \"d2\": 0.607, \"d3\": 0.761}, \"three_class_precision\": {\"d1\": 0.863, \"d2\": 0.646, \"d3\": 0.718}, \"four_class_per_class\": {\"d0\": {\"precision\": 0.95, \"recall\": 0.99, \"f1\": 0.97}, \"d1\": {\"precision\": 0.85, \"recall\": 0.82, \"f1\": 0.83}, \"d2\": {\"precision\": 0.63, \"recall\": 0.59, \"f1\": 0.61}, \"d3\": {\"precision\": 0.71, \"recall\": 0.76, \"f1\": 0.73}}, \"finetune_losses\": {\"depth_0\": 2.269, \"depth_1\": 1.65, \"depth_2\": 1.226}, \"top_features\": [\"p90_ppl (0.18)\", \"var_surprisal (0.16)\", \"p75_ppl (0.11)\", \"mean_surprisal (0.08)\", \"type_token_ratio (0.06)\"], \"code_contamination\": {\"d0\": 0.005, \"d1\": 0.027, \"d2\": 0.007, \"d3\": 0.008}, \"feature_dim\": 19, \"truncation_length\": 507}}, \"pythia_temp09_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T14:49:27.459Z\", \"updated_at\": \"2026-05-14T16:46:11.832Z\", \"hypothesis\": \"解码策略鲁棒性: Pythia-1.4B 在 temperature-only τ=0.9 下递归生成的深度信号与 nucleus p=0.95 一致，支持跨策略泛化\", \"metrics\": {\"four_class\": {\"rf_accuracy\": 0.7625, \"rf_accuracy_ci\": [0.749, 0.7753], \"lr_accuracy\": 0.7405, \"lr_accuracy_ci\": [0.7265, 0.7545], \"pairwise_auc\": {\"0v1\": 0.9968, \"0v2\": 0.9993, \"0v3\": 0.9991, \"1v2\": 0.8327, \"1v3\": 0.959, \"2v3\": 0.7928}, \"top_features\": [\"var_surprisal (0.1776)\", \"p90_ppl (0.1501)\", \"mean_ppl (0.1140)\", \"mean_surprisal (0.0889)\", \"p75_ppl (0.0687)\"], \"feature_dim\": 19, \"truncation_length\": 498}, \"three_class_full\": {\"accuracy\": 0.6983, \"accuracy_ci\": [0.682, 0.715], \"mae\": 0.3357, \"recall\": {\"d1\": 0.802, \"d2\": 0.554, \"d3\": 0.739}, \"precision\": {\"d1\": 0.792, \"d2\": 0.608, \"d3\": 0.686}, \"f1\": {\"d1\": 0.797, \"d2\": 0.58, \"d3\": 0.712}, \"pairwise_auc\": {\"d1v2\": 0.8354, \"d1v3\": 0.9631, \"d2v3\": 0.8043}}, \"three_class_filtered\": {\"accuracy\": 0.7252, \"accuracy_ci\": [0.7064, 0.7427], \"mae\": 0.2953, \"recall\": {\"d1\": 0.842, \"d2\": 0.596, \"d3\": 0.735}, \"precision\": {\"d1\": 0.821, \"d2\": 0.628, \"d3\": 0.715}, \"f1\": {\"d1\": 0.831, \"d2\": 0.611, \"d3\": 0.725}, \"pairwise_auc\": {\"d1v2\": 0.8656, \"d1v3\": 0.9772, \"d2v3\": 0.8295}, \"n_samples\": 11445, \"n_removed\": 3555}, \"finetune_losses\": {\"depth_0\": 2.222, \"depth_1\": 1.37, \"depth_2\": 1.006}, \"code_contamination\": {\"d0\": 0.004, \"d1\": 0.077, \"d2\": 0.116, \"d3\": 0.136}}, \"conclusion\": \"success\", \"notes\": \"## Comparison: temp_only τ=0.9 vs baseline nucleus p=0.95\\n\\n### 4-class classification (d0-d3)\\n| Metric | Baseline (nucleus p=0.95) | Temp09 (τ=0.9) | Δ |\\n|--------|--------------------------|-----------------|---|\\n| RF acc | 78.15% [76.9, 79.4] | 76.25% [74.9, 77.5] | -1.9pp |\\n| LR acc | 74.92% | 74.05% | -0.9pp |\\n| AUC 0v1 | 0.9975 | 0.9968 | -0.0007 |\\n| AUC 1v2 | 0.8607 | 0.8327 | -0.028 |\\n| AUC 2v3 | 0.8005 | 0.7928 | -0.008 |\\n\\n### 3-class classification (d1-d3 only)\\n| Metric | Baseline | Temp09 | Δ |\\n|--------|----------|--------|---|\\n| Full acc | 70.8% | 69.83% | -1.0pp |\\n| Filtered acc | — | 72.52% [70.6, 74.3] | — |\\n| Filtered d1v2 AUC | — | 0.8656 | — |\\n| Filtered d2v3 AUC | — | 0.8295 | — |\\n\\n### Feature importance (top-5, same ranking)\\n1. var_surprisal (0.178 vs 0.169)\\n2. p90_ppl (0.150 vs 0.158)\\n3. mean_ppl (0.114 vs 0.120)\\n4. mean_surprisal (0.089 vs 0.088)\\n5. p75_ppl (0.069 vs 0.067)\\n\\n### Code contamination\\n| Depth | Baseline | Temp09 | Δ |\\n|-------|----------|--------|---|\\n| d1 | 5.0% | 7.7% | +2.7pp |\\n| d2 | 9.0% | 11.6% | +2.6pp |\\n| d3 | 12.0% | 13.6% | +1.6pp |\\n\\n### Analysis\\n1. **Depth signal robust across decoding strategies**: temp_only τ=0.9 achieves 76.25% 4-class acc (vs 78.15% baseline), only 1.9pp lower — well within the hypothesis that depth signal is decoding-strategy-agnostic.\\n2. **Ordinal structure preserved**: AUC ordering 0v1 > 1v3 > 1v2 > 2v3 identical to baseline, confirming the difficulty gradient d0≫d1>d2>d3 is robust.\\n3. **d2 remains the weak link**: d2 recall (0.554 in 3-class) is the lowest, consistent with baseline — d2 is the hardest to distinguish from both d1 and d3.\\n4. **Feature importance stable**: Top-5 features identical between strategies with near-identical importance weights, suggesting the same statistical signatures carry depth information regardless of decoding method.\\n5. **Higher code contamination**: Temp09 shows 2-3pp higher code-like content across depths, possibly because temperature-only sampling without top-p truncation preserves more of the distribution tail including code patterns. The filtered 3-class acc (72.52%) mitigates this.\\n6. **Conclusion: SUCCESS** — 4-class acc 76.25% >> 40% threshold, d1v2 AUC 0.8327 >> 0.6 threshold. Hypothesis confirmed: temperature-only decoding preserves recursive depth signal.\"}, \"mvp_pipeline_pythia_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T12:07:25.860Z\", \"updated_at\": \"2026-05-14T16:13:24.461Z\", \"metrics\": {\"full_4class_acc\": 0.782, \"full_4class_acc_ci\": [0.769, 0.794], \"full_4class_acc_stratified\": 0.781, \"full_mae\": 0.2367, \"full_auc_0v1\": 0.9975, \"full_auc_1v2\": 0.8607, \"full_auc_2v3\": 0.8005, \"filtered_4class_acc\": 0.816, \"filtered_4class_acc_ci\": [0.803, 0.829], \"filtered_mae\": 0.1995, \"filtered_auc_0v1\": 0.9977, \"filtered_auc_1v2\": 0.8782, \"filtered_auc_2v3\": 0.8323, \"filtered_sample_count\": 16993, \"three_class_acc\": 0.708, \"three_class_acc_ci\": [0.692, 0.725], \"three_class_mae\": 0.3203, \"three_class_auc_1v2\": 0.854, \"three_class_auc_1v3\": 0.9569, \"three_class_auc_2v3\": 0.7931, \"three_class_recall_d1\": 0.79, \"three_class_recall_d2\": 0.607, \"three_class_recall_d3\": 0.728, \"three_class_precision_d1\": 0.852, \"three_class_precision_d2\": 0.605, \"three_class_precision_d3\": 0.68, \"three_class_f1_d1\": 0.82, \"three_class_f1_d2\": 0.606, \"three_class_f1_d3\": 0.703, \"three_class_lr_acc\": 0.671, \"filtered_three_class_acc\": 0.747, \"filtered_three_class_acc_ci\": [0.727, 0.764], \"filtered_three_class_mae\": 0.2759, \"filtered_three_class_recall_d1\": 0.862, \"filtered_three_class_recall_d2\": 0.635, \"filtered_three_class_recall_d3\": 0.735, \"filtered_three_class_precision_d1\": 0.867, \"filtered_three_class_precision_d2\": 0.659, \"filtered_three_class_precision_d3\": 0.704, \"filtered_three_class_f1_d1\": 0.864, \"filtered_three_class_f1_d2\": 0.647, \"filtered_three_class_f1_d3\": 0.719, \"filtered_three_class_auc_1v2\": 0.8926, \"filtered_three_class_auc_1v3\": 0.9769, \"filtered_three_class_auc_2v3\": 0.8272, \"filtered_three_class_sample_count\": 12012, \"best_model\": \"RandomForest\", \"top_features\": [\"var_surprisal\", \"p90_ppl\", \"mean_ppl\", \"mean_surprisal\", \"p75_ppl\"], \"truncation_length\": 498, \"feature_dim\": 19}, \"conclusion\": \"success\"}, \"cross_model_olmo_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T14:10:48.599Z\", \"updated_at\": \"2026-05-14T14:52:05.061Z\", \"metrics\": {\"status\": \"PIPELINE_CRASHED\", \"completed_steps\": [\"depth0_lora_finetune\"], \"failed_at\": \"shell_script_line_52_unmatched_quote\", \"depth0_final_loss\": 2.2686, \"depth0_train_runtime_s\": 283.2, \"depth0_train_steps\": 939, \"depth0_trainable_params\": 3145728, \"depth0_total_params\": 1179910144, \"classification_results\": null, \"note\": \"Script crashed after depth-0 finetune. No depth-1/2/3 generation, no feature extraction, no classification performed.\"}, \"conclusion\": \"failed\"}, \"mvp_pipeline_qwen_base_004\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T11:49:48.916Z\", \"updated_at\": \"2026-05-14T12:07:13.745Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_pythia_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T11:38:38.070Z\", \"updated_at\": \"2026-05-14T12:07:13.387Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_base_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T11:15:05.767Z\", \"updated_at\": \"2026-05-14T12:07:12.480Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_003\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T10:21:35.653Z\", \"updated_at\": \"2026-05-14T12:07:11.506Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_002\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T10:21:10.897Z\", \"updated_at\": \"2026-05-14T12:07:10.599Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_001\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T10:14:38.727Z\", \"updated_at\": \"2026-05-14T12:07:10.095Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_base_003\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T11:16:25.669Z\", \"updated_at\": \"2026-05-14T11:26:12.749Z\", \"conclusion\": \"killed\"}, \"mvp_pipeline_004\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T10:23:02.280Z\", \"updated_at\": \"2026-05-14T11:05:26.253Z\", \"conclusion\": \"killed\"}}, \"count\": 46, \"total\": 46, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.246}}"
    }
  },
  "sourceToolAssistantUUID": "5533e823-d7f4-4d44-b5ac-5f8971f26bd8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 27 · 2026-05-15T15:21:04.402Z_

<details open><summary>🔧 Tool call — Read · `toolu_016xozFvBpS2x59XwghnKA1f`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6ca89540-3e58-4d3c-9473-a5bd3fa4ec72",
  "isSidechain": false,
  "requestId": "req_011Cb4ag31UzoTuNnEJ6SbW5",
  "type": "assistant",
  "uuid": "a452d4d5-69cb-46b4-90ee-4d79272d5cd4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015C6mG9WRpRE4rX9MPu9dnr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17139,
      "cache_read_input_tokens": 31077,
      "output_tokens": 330,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17139,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 330,
          "cache_read_input_tokens": 31077,
          "cache_creation_input_tokens": 17139,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17139
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-15T15:21:04.408Z_

<details><summary>↩ Tool result · `toolu_016xozFvBpS2x59XwghnKA1f`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Depth-graduated data curation.}
5	Predicted depth can serve as a continuous quality proxy for importance weighting in curation pipelines \cite{dsir2023,qurating2024}, retaining shallow-generation text while down-weighting deeply recursive samples that binary filters \cite{drayson2025_detection_prevents_collapse} would indiscriminately discard.
6	
7	\paragraph{Deployment considerations.}
8	The temperature-induced d1/d2 AUC inversion (\S\ref{sec:gen:crossstrategy}) means deploying without knowing the target decoding strategy risks systematic prediction reversals; strategy-conditioned classifiers or automatic strategy identification are needed.
9	
10	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a452d4d5-69cb-46b4-90ee-4d79272d5cd4",
  "isSidechain": false,
  "promptId": "c35df68b-0435-45c4-bd46-57fc93e3c537",
  "type": "user",
  "uuid": "db40aa4d-437b-415b-9c85-92b718e294ae",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Depth-graduated data curation.}\nPredicted depth can serve as a continuous quality proxy for importance weighting in curation pipelines \\cite{dsir2023,qurating2024}, retaining shallow-generation text while down-weighting deeply recursive samples that binary filters \\cite{drayson2025_detection_prevents_collapse} would indiscriminately discard.\n\n\\paragraph{Deployment considerations.}\nThe temperature-induced d1/d2 AUC inversion (\\S\\ref{sec:gen:crossstrategy}) means deploying without knowing the target decoding strategy risks systematic prediction reversals; strategy-conditioned classifiers or automatic strategy identification are needed.\n\n",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  },
  "sourceToolAssistantUUID": "a452d4d5-69cb-46b4-90ee-4d79272d5cd4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-15T15:21:05.048Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NfoRCCrUEH1CX3M2H3z3sc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "db40aa4d-437b-415b-9c85-92b718e294ae",
  "isSidechain": false,
  "requestId": "req_011Cb4ag31UzoTuNnEJ6SbW5",
  "type": "assistant",
  "uuid": "f2dd80b1-e80a-4b5b-b278-b4cee310b954",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015C6mG9WRpRE4rX9MPu9dnr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17139,
      "cache_read_input_tokens": 31077,
      "output_tokens": 330,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17139,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 330,
          "cache_read_input_tokens": 31077,
          "cache_creation_input_tokens": 17139,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17139
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Runtime record

_source line 30 · 2026-05-15T15:21:05.097Z_

```json
{
  "parentUuid": "d2c97c11-2194-46db-b83d-796bb503df33",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "d5eeb81e-7c19-4026-88cc-502aa2af5876",
  "timestamp": "2026-05-15T15:21:05.097Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/reviewer_2647e3b4",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 31_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Paper Agent 触发审查]: ## 审查请求 — Reviewer Round 2（3处修复）  **writing_plan**: `projects/recursive_gen_depth_est/writing_plan.yaml` **Paper dir**: `projects/recursive_gen_depth_est/docs/paper/` **编译状态**: 11页…",
  "leafUuid": "d5eeb81e-7c19-4026-88cc-502aa2af5876",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655"
}
```

---

### Runtime record

_source line 32_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper revisions for recursive depth estimation",
  "sessionId": "6797ed9c-81cb-4a78-af4b-6d104e682655"
}
```

---

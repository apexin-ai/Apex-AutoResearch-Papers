# Research conversation: [Round 1 审稿请求]: 你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。 ## Venue 信息 - **目标**: EMNLP 2026 (ARR May 2026 cycle) - **截止

**Output-Distribution Distillation for Contextual Sparsity Prediction in SwiGLU LLMs (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 69
- **Recorded user turns:** 3
- **Tool calls:** 18
- **Original source:** `logs/chats/exported-trajectories/account-2/5312a086-3c80-45ff-89ba-6f1086157f10.jsonl`
- **Structured JSON:** [`8ac4b7d8c28a582446d0.json`](../../sessions/8a/8ac4b7d8c28a582446d0.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-18T12:24:26.157Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-18T12:24:26.157Z",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "content": "[Round 1 审稿请求]:\n你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。\n\n## Venue 信息\n- **目标**: EMNLP 2026 (ARR May 2026 cycle)\n- **截止日期**: 2026-05-25\n- **格式**: ACL style, Long paper ≤8 页正文, double-blind\n- **评分标准**: 5=Award(前2.5%), 4=Conference(主会议), 3=Findings, 2=Resubmit, 1=Do not resubmit\n\n## 论文路径\n`projects/distill_sparse_swiglu/paper/main.tex`\n（含 abstract.tex, introduction.tex, method.tex, experiments.tex, related_work.tex, conclusion.tex, limitations.tex, ethics.tex, appendix.tex）\n\n## 论文概要\n提出用 forward KL 蒸馏（替代 BCE）训练 SwiGLU LLM 的激活稀疏性预测器。核心论点：BCE 的 per-neuron 梯度与 TEAL 的 global top-k 推理分配存在结构性错配；KL 通过端到端梯度耦合解决此问题。在 LLaMA-3.1-8B 上，KL predictor (<1% params) 在 30% 稀疏度下 PPL 降低 18%，在 50% 下降低 49%，且 compensation network 冗余。跨架构验证涵盖 Mistral-7B 和 Qwen-2.5-14B。\n\n## 你的审查重点\n\n### 方法严谨性\n1. **梯度分析 (§3.5)**: BCE vs KL 梯度结构分析是否严谨？\"structural mismatch\" 论证是否过度包装了一个基本原理（end-to-end > decomposed）？SNR 测量的统计力度（步数、CI、替代解释）。\n2. **Gumbel-Sigmoid 松弛 (§3.3)**: 训练（soft mask）和推理（hard mask via TEAL top-k）之间的 gap 是否被充分量化？\n3. **自适应惩罚控制器 (§3.5)**: 30% 目标偏差 5%（实际 28.5%），对 TEAL 对比的影响是否讨论清楚？术语是否准确？\n4. **BCE 对比公平性 (§4.2-4.3)**: KL 与 BCE 的差异是 loss function 差异还是 pipeline 差异（oracle 来源、Gumbel vs hard mask、penalty vs threshold）？confound 是否被承认？\n\n### 实验充分性\n5. **统计效力**: 主表中多少结果有 multi-seed？单 seed 结果的可靠性？Gumbel 随机性是否被充分考虑？\n6. **OOD 评估**: 训练用 WikiText-103、评测用 WikiText-2（同源）。C4 OOD 覆盖哪些 sparsity levels？\n7. **跨架构/跨规模**: Mistral 仅 PPL 无 downstream？Qwen-14B 的 MMLU gap 是否被充分分析？\n8. **Regime 分析 (Table 4)**: 3 个采样点（30/40/50%）是否足够支撑 \"three operating regions\" 的结论？\n9. **Compensation 冗余 claim**: KL+compensation 控制实验是否存在？数据是否充分？\n\n请按 ACL 审稿标准输出完整审稿报告：Summary → Strengths → Weaknesses (Must-Fix / Should-Fix / Minor) → Questions → Missing References → Overall Assessment (评分+置信度)。"
}
```

---

### Runtime record

_source line 2 · 2026-05-18T12:24:26.162Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-18T12:24:26.162Z",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

## Round 1

62 recorded events

### User

_source line 3 · 2026-05-18T12:24:26.197Z_

[Round 1 审稿请求]:
你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。

## Venue 信息
- **目标**: EMNLP 2026 (ARR May 2026 cycle)
- **截止日期**: 2026-05-25
- **格式**: ACL style, Long paper ≤8 页正文, double-blind
- **评分标准**: 5=Award(前2.5%), 4=Conference(主会议), 3=Findings, 2=Resubmit, 1=Do not resubmit

## 论文路径
`projects/distill_sparse_swiglu/paper/main.tex`
（含 abstract.tex, introduction.tex, method.tex, experiments.tex, related_work.tex, conclusion.tex, limitations.tex, ethics.tex, appendix.tex）

## 论文概要
提出用 forward KL 蒸馏（替代 BCE）训练 SwiGLU LLM 的激活稀疏性预测器。核心论点：BCE 的 per-neuron 梯度与 TEAL 的 global top-k 推理分配存在结构性错配；KL 通过端到端梯度耦合解决此问题。在 LLaMA-3.1-8B 上，KL predictor (<1% params) 在 30% 稀疏度下 PPL 降低 18%，在 50% 下降低 49%，且 compensation network 冗余。跨架构验证涵盖 Mistral-7B 和 Qwen-2.5-14B。

## 你的审查重点

### 方法严谨性
1. **梯度分析 (§3.5)**: BCE vs KL 梯度结构分析是否严谨？"structural mismatch" 论证是否过度包装了一个基本原理（end-to-end > decomposed）？SNR 测量的统计力度（步数、CI、替代解释）。
2. **Gumbel-Sigmoid 松弛 (§3.3)**: 训练（soft mask）和推理（hard mask via TEAL top-k）之间的 gap 是否被充分量化？
3. **自适应惩罚控制器 (§3.5)**: 30% 目标偏差 5%（实际 28.5%），对 TEAL 对比的影响是否讨论清楚？术语是否准确？
4. **BCE 对比公平性 (§4.2-4.3)**: KL 与 BCE 的差异是 loss function 差异还是 pipeline 差异（oracle 来源、Gumbel vs hard mask、penalty vs threshold）？confound 是否被承认？

### 实验充分性
5. **统计效力**: 主表中多少结果有 multi-seed？单 seed 结果的可靠性？Gumbel 随机性是否被充分考虑？
6. **OOD 评估**: 训练用 WikiText-103、评测用 WikiText-2（同源）。C4 OOD 覆盖哪些 sparsity levels？
7. **跨架构/跨规模**: Mistral 仅 PPL 无 downstream？Qwen-14B 的 MMLU gap 是否被充分分析？
8. **Regime 分析 (Table 4)**: 3 个采样点（30/40/50%）是否足够支撑 "three operating regions" 的结论？
9. **Compensation 冗余 claim**: KL+compensation 控制实验是否存在？数据是否充分？

请按 ACL 审稿标准输出完整审稿报告：Summary → Strengths → Weaknesses (Must-Fix / Should-Fix / Minor) → Questions → Missing References → Overall Assessment (评分+置信度)。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "ba913126-43de-40a8-9dcb-490441b457d0",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-18T12:24:26.196Z_

```json
{
  "parentUuid": "ba913126-43de-40a8-9dcb-490441b457d0",
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
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
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
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "f5bc775b-43a8-4005-85cd-ba979e9a5a2a",
  "timestamp": "2026-05-18T12:24:26.196Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-18T12:24:26.196Z_

```json
{
  "parentUuid": "f5bc775b-43a8-4005-85cd-ba979e9a5a2a",
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
  "uuid": "91e89ae6-44a9-4126-86e1-579638180480",
  "timestamp": "2026-05-18T12:24:26.196Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 6 · 2026-05-18T12:24:26.196Z_

```json
{
  "parentUuid": "91e89ae6-44a9-4126-86e1-579638180480",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "bc1df317-1be7-4a2a-bcc4-35c6dbc173f2",
  "timestamp": "2026-05-18T12:24:26.196Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 7_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Assistant

_source line 8 · 2026-05-18T12:24:29.492Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to perform a thorough review of a paper as Reviewer 1 for EMNLP 2026. I need to:

1. First, run the session start skill
2. Search for ACL ARR reviewer guidelines
3. Read the paper thoroughly
4. Produce a detailed review

Let me start by reading the paper and searching for reviewer guidelines.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bc1df317-1be7-4a2a-bcc4-35c6dbc173f2",
  "isSidechain": false,
  "requestId": "req_011CbA2e9BJ8YsM2PPPVPxq1",
  "type": "assistant",
  "uuid": "c92493e3-b89e-41e6-b103-0a772ac552a0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TjC3idcgBrLGiww233XmrS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 16192,
      "cache_read_input_tokens": 11841,
      "output_tokens": 260,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 16192,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 260,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 16192,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 16192
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

_source line 9 · 2026-05-18T12:24:30.492Z_

开始 Round 7 审稿。先加载论文并搜索 ACL ARR 官方审稿标准。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c92493e3-b89e-41e6-b103-0a772ac552a0",
  "isSidechain": false,
  "requestId": "req_011CbA2e9BJ8YsM2PPPVPxq1",
  "type": "assistant",
  "uuid": "b6646213-04b9-4dcf-94e2-bb18ee833864",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TjC3idcgBrLGiww233XmrS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 16192,
      "cache_read_input_tokens": 11841,
      "output_tokens": 260,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 16192,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 260,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 16192,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 16192
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

_source line 10 · 2026-05-18T12:24:32.694Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01EpWkdJoZ7RYjLzXMAisQ7K`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references,WebSearch,WebFetch",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b6646213-04b9-4dcf-94e2-bb18ee833864",
  "isSidechain": false,
  "requestId": "req_011CbA2e9BJ8YsM2PPPVPxq1",
  "type": "assistant",
  "uuid": "c86712dc-a27c-40a0-b594-78d330804448",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TjC3idcgBrLGiww233XmrS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 16192,
      "cache_read_input_tokens": 11841,
      "output_tokens": 260,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 16192,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 260,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 16192,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 16192
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

_source line 11 · 2026-05-18T12:24:32.701Z_

<details><summary>↩ Tool result · `toolu_01EpWkdJoZ7RYjLzXMAisQ7K`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__pdf_to_images"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__review_reviewer_post_to_director"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__verify_references"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "WebSearch"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "WebFetch"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c86712dc-a27c-40a0-b594-78d330804448",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "422e0ccd-7511-4f12-9e45-55c13d2ddb59",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references",
      "WebSearch",
      "WebFetch"
    ],
    "query": "select:mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references,WebSearch,WebFetch",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "c86712dc-a27c-40a0-b594-78d330804448",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 12 · 2026-05-18T12:24:35.408Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me search for ACL ARR reviewer guidelines and read the paper simultaneously.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "422e0ccd-7511-4f12-9e45-55c13d2ddb59",
  "isSidechain": false,
  "requestId": "req_011CbA2ed2MzrG9MLLehM62Y",
  "type": "assistant",
  "uuid": "6ab700b5-48a7-45da-8460-bc92c2fc2fb9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CeCjqYWwWRsmJmJvhda1Xp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2256,
      "cache_read_input_tokens": 28033,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 184,
          "cache_read_input_tokens": 28033,
          "cache_creation_input_tokens": 2256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2256
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

_source line 13 · 2026-05-18T12:24:35.898Z_

<details open><summary>🔧 Tool call — WebSearch · `toolu_01BroefNbWSBAq8oqxyEbWcG`</summary>

```json
{
  "query": "ACL ARR 2025 2026 reviewer guidelines review form criteria scoring"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6ab700b5-48a7-45da-8460-bc92c2fc2fb9",
  "isSidechain": false,
  "requestId": "req_011CbA2ed2MzrG9MLLehM62Y",
  "type": "assistant",
  "uuid": "9ea30f60-c98d-493d-890e-d74b6a31e79d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CeCjqYWwWRsmJmJvhda1Xp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2256,
      "cache_read_input_tokens": 28033,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 184,
          "cache_read_input_tokens": 28033,
          "cache_creation_input_tokens": 2256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2256
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

_source line 14 · 2026-05-18T12:24:37.743Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01CFb1RWFBeP7JnJCmj9npKz`</summary>

```json
{
  "pattern": "projects/distill_sparse_swiglu/paper/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9ea30f60-c98d-493d-890e-d74b6a31e79d",
  "isSidechain": false,
  "requestId": "req_011CbA2ed2MzrG9MLLehM62Y",
  "type": "assistant",
  "uuid": "cc113a50-1bfc-45e0-817e-3a4260d6ef8b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CeCjqYWwWRsmJmJvhda1Xp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2256,
      "cache_read_input_tokens": 28033,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 184,
          "cache_read_input_tokens": 28033,
          "cache_creation_input_tokens": 2256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2256
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

_source line 15 · 2026-05-18T12:24:37.777Z_

<details><summary>↩ Tool result · `toolu_01CFb1RWFBeP7JnJCmj9npKz`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cc113a50-1bfc-45e0-817e-3a4260d6ef8b",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "6b8f0378-636a-4f83-93b4-ad0cb4f3cb35",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 27,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "cc113a50-1bfc-45e0-817e-3a4260d6ef8b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-18T12:24:44.107Z_

<details><summary>↩ Tool result · `toolu_01BroefNbWSBAq8oqxyEbWcG`</summary>

```text
Web search results for query: "ACL ARR 2025 2026 reviewer guidelines review form criteria scoring"

Links: [{"title":"ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewerguidelines"},{"title":"ARR Area Chair Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/acguidelines"},{"title":"CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/cfp"},{"title":"Review Form – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewform"},{"title":"ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/"},{"title":"aclrollingreview/cfp.md at main · acl-org/aclrollingreview","url":"https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"},{"title":"How ARR works – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewing"},{"title":"Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/authors"},{"title":"ACLRollingReview (@ReviewAcl) / Posts / X","url":"https://x.com/ReviewAcl"},{"title":"aclrollingreview/reviewing.md at main · acl-org/aclrollingreview","url":"https://github.com/acl-org/aclrollingreview/blob/main/reviewing.md"}]

Based on the search results, here is information about ACL ARR 2025-2026 reviewer guidelines, review form criteria, and scoring:

## Reviewer Scoring System

Starting with February 2025, ARR reviewers are asked to provide three scores: soundness, excitement, and overall recommendation. The soundness scores must be justified by the text of the review.

## Overall Recommendation Scale

The review form includes the following recommendation options:

- 5 = Consider for Award: I think this paper could be considered for an outstanding paper award at an *ACL conference (up to top 2.5% papers).
- 2 = Resubmit next cycle: I think this paper needs substantial revisions that can be completed by the next ARR cycle.
- 1.5 = Resubmit after next cycle: I think this paper needs substantial revisions that cannot be completed by the next ARR cycle.
- 1 = Do not resubmit: This paper has to be fully redone, or it is not relevant to the *ACL community (e.g. it is in no way related to computational processing of language).

## Area Chair (Meta-Review) Scoring

The ARR metareview score has changed in February 2025 to be more aligned with reviewer scores.

## Review Criteria

Key review form criteria include questions about:

- Whether authors have adequately discussed the limitations and potential positive and negative societal impacts of their work, with constructive suggestions for improvement if not.
- Whether there is enough information in the paper for a reader to reproduce the main results, use results presented in this paper in future work (e.g., as a baseline), or build upon this work.

For the complete official guidelines, you can visit the [ARR Reviewer Guidelines page](http://aclrollingreview.org/reviewerguidelines) and [Review Form page](http://aclrollingreview.org/reviewform).


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9ea30f60-c98d-493d-890e-d74b6a31e79d",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "2ced3744-d49e-428c-b23f-acea3d521fb4",
  "toolUseResult": {
    "query": "ACL ARR 2025 2026 reviewer guidelines review form criteria scoring",
    "results": [
      {
        "tool_use_id": "srvtoolu_011yawuroJCRdkJ7oSMuuKES",
        "content": [
          {
            "title": "ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/reviewerguidelines"
          },
          {
            "title": "ARR Area Chair Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/acguidelines"
          },
          {
            "title": "CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/cfp"
          },
          {
            "title": "Review Form – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/reviewform"
          },
          {
            "title": "ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/"
          },
          {
            "title": "aclrollingreview/cfp.md at main · acl-org/aclrollingreview",
            "url": "https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"
          },
          {
            "title": "How ARR works – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/reviewing"
          },
          {
            "title": "Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/authors"
          },
          {
            "title": "ACLRollingReview (@ReviewAcl) / Posts / X",
            "url": "https://x.com/ReviewAcl"
          },
          {
            "title": "aclrollingreview/reviewing.md at main · acl-org/aclrollingreview",
            "url": "https://github.com/acl-org/aclrollingreview/blob/main/reviewing.md"
          }
        ]
      },
      "Based on the search results, here is information about ACL ARR 2025-2026 reviewer guidelines, review form criteria, and scoring:\n\n## Reviewer Scoring System\n\nStarting with February 2025, ARR reviewers are asked to provide three scores: soundness, excitement, and overall recommendation. The soundness scores must be justified by the text of the review.\n\n## Overall Recommendation Scale\n\nThe review form includes the following recommendation options:\n\n- 5 = Consider for Award: I think this paper could be considered for an outstanding paper award at an *ACL conference (up to top 2.5% papers).\n- 2 = Resubmit next cycle: I think this paper needs substantial revisions that can be completed by the next ARR cycle.\n- 1.5 = Resubmit after next cycle: I think this paper needs substantial revisions that cannot be completed by the next ARR cycle.\n- 1 = Do not resubmit: This paper has to be fully redone, or it is not relevant to the *ACL community (e.g. it is in no way related to computational processing of language).\n\n## Area Chair (Meta-Review) Scoring\n\nThe ARR metareview score has changed in February 2025 to be more aligned with reviewer scores.\n\n## Review Criteria\n\nKey review form criteria include questions about:\n\n- Whether authors have adequately discussed the limitations and potential positive and negative societal impacts of their work, with constructive suggestions for improvement if not.\n- Whether there is enough information in the paper for a reader to reproduce the main results, use results presented in this paper in future work (e.g., as a baseline), or build upon this work.\n\nFor the complete official guidelines, you can visit the [ARR Reviewer Guidelines page](http://aclrollingreview.org/reviewerguidelines) and [Review Form page](http://aclrollingreview.org/reviewform)."
    ],
    "durationSeconds": 8.202287013000001
  },
  "sourceToolAssistantUUID": "9ea30f60-c98d-493d-890e-d74b6a31e79d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-18T12:24:48.569Z_

<details open><summary>🔧 Tool call — WebFetch · `toolu_01XqjGUu2i9RAW4j4eYaWF43`</summary>

```json
{
  "url": "https://aclrollingreview.org/reviewform",
  "prompt": "Extract the complete ACL ARR review form: all scoring dimensions (soundness, excitement, overall assessment, confidence, etc.), their scales, and descriptions. Include all questions reviewers must answer."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2ced3744-d49e-428c-b23f-acea3d521fb4",
  "isSidechain": false,
  "requestId": "req_011CbA2fTkn4jtQNUxHW1ciz",
  "type": "assistant",
  "uuid": "130bd4cb-07fc-4964-9f03-cf47d354c42e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EK5MGv1KQABdqXRT3ZsC17",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 34,
      "cache_creation_input_tokens": 1136,
      "cache_read_input_tokens": 30289,
      "output_tokens": 205,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1136,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 34,
          "output_tokens": 205,
          "cache_read_input_tokens": 30289,
          "cache_creation_input_tokens": 1136,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1136
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

_source line 18 · 2026-05-18T12:24:49.357Z_

<details open><summary>🔧 Tool call — Glob · `toolu_014YaHaTBDbeE7341T8GHcP5`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "130bd4cb-07fc-4964-9f03-cf47d354c42e",
  "isSidechain": false,
  "requestId": "req_011CbA2fTkn4jtQNUxHW1ciz",
  "type": "assistant",
  "uuid": "9dee0614-8883-4c31-a252-9314e46d1f8d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EK5MGv1KQABdqXRT3ZsC17",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 34,
      "cache_creation_input_tokens": 1136,
      "cache_read_input_tokens": 30289,
      "output_tokens": 205,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1136,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 34,
          "output_tokens": 205,
          "cache_read_input_tokens": 30289,
          "cache_creation_input_tokens": 1136,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1136
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

_source line 19 · 2026-05-18T12:24:49.371Z_

<details><summary>↩ Tool result · `toolu_014YaHaTBDbeE7341T8GHcP5`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/ethics.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/limitations.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9dee0614-8883-4c31-a252-9314e46d1f8d",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "96d36f2f-b034-4764-8343-216de7b45b8d",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/ethics.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/related_work.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/limitations.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/method.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/experiments.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/abstract.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/introduction.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/appendix.tex"
    ],
    "durationMs": 8,
    "numFiles": 10,
    "truncated": false
  },
  "sourceToolAssistantUUID": "9dee0614-8883-4c31-a252-9314e46d1f8d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 20_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。  ## Venue 信息 - **目标**: EMNLP 2026 (ARR May 2026 cycle) - **截止日期**: 2026-05-25 - **格式**: ACL style, Long paper ≤8 页正文, double-blind - **评分标准*…",
  "leafUuid": "96d36f2f-b034-4764-8343-216de7b45b8d",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Tool result

_source line 22 · 2026-05-18T12:24:53.919Z_

<details><summary>↩ Tool result · `toolu_01XqjGUu2i9RAW4j4eYaWF43`</summary>

```text
# ACL ARR Review Form: Scoring Dimensions and Questions

## Primary Scoring Dimensions

**Reviewer Confidence** (1-5 scale)
- 5: "Positive that my evaluation is correct"
- 4: "Quite sure"
- 3: "Pretty sure, but there's a chance I missed something"
- 2: "Willing to defend my evaluation, but it is fairly likely that I missed some details"
- 1: "Not my area, or paper is very hard to understand"

**Soundness** (1-5 scale with half-point increments)
- 5: Excellent thoroughness for paper type
- 4: Provides sufficient support for claims
- 3: Adequate support for main claims
- 2: Major technical/methodological problems
- 1: Insufficient rigor for publication

**Excitement** (1-5 scale with half-point increments)
- 5: "I would recommend this paper to others"
- 4: "I would mention this paper to others"
- 3: "I might mention some points"
- 2: "Does not resonate with me"
- 1: "Not Exciting"

**Overall Assessment** (1-5 scale with half-point increments)
- 5: Award consideration
- 4: Conference acceptance
- 3: Findings acceptance
- 2: Resubmit next cycle
- 1: Do not resubmit

## Required Written Sections

- Paper Summary
- Summary of Strengths
- Summary of Weaknesses
- Comments/Suggestions/Typos
- Best paper justification (if applicable)
- Limitations and Societal Impact
- Ethical Concerns
- Reproducibility (1-5 scale)
- Datasets (1-5 scale)
- Software (1-5 scale)
- Author Identity Knowledge (1-5 scale)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "130bd4cb-07fc-4964-9f03-cf47d354c42e",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "6d7de2e4-3724-4207-8cc0-5b830f3645ed",
  "toolUseResult": {
    "bytes": 25365,
    "code": 200,
    "codeText": "OK",
    "result": "# ACL ARR Review Form: Scoring Dimensions and Questions\n\n## Primary Scoring Dimensions\n\n**Reviewer Confidence** (1-5 scale)\n- 5: \"Positive that my evaluation is correct\"\n- 4: \"Quite sure\"\n- 3: \"Pretty sure, but there's a chance I missed something\"\n- 2: \"Willing to defend my evaluation, but it is fairly likely that I missed some details\"\n- 1: \"Not my area, or paper is very hard to understand\"\n\n**Soundness** (1-5 scale with half-point increments)\n- 5: Excellent thoroughness for paper type\n- 4: Provides sufficient support for claims\n- 3: Adequate support for main claims\n- 2: Major technical/methodological problems\n- 1: Insufficient rigor for publication\n\n**Excitement** (1-5 scale with half-point increments)\n- 5: \"I would recommend this paper to others\"\n- 4: \"I would mention this paper to others\"\n- 3: \"I might mention some points\"\n- 2: \"Does not resonate with me\"\n- 1: \"Not Exciting\"\n\n**Overall Assessment** (1-5 scale with half-point increments)\n- 5: Award consideration\n- 4: Conference acceptance\n- 3: Findings acceptance\n- 2: Resubmit next cycle\n- 1: Do not resubmit\n\n## Required Written Sections\n\n- Paper Summary\n- Summary of Strengths\n- Summary of Weaknesses\n- Comments/Suggestions/Typos\n- Best paper justification (if applicable)\n- Limitations and Societal Impact\n- Ethical Concerns\n- Reproducibility (1-5 scale)\n- Datasets (1-5 scale)\n- Software (1-5 scale)\n- Author Identity Knowledge (1-5 scale)",
    "durationMs": 5346,
    "url": "https://aclrollingreview.org/reviewform"
  },
  "sourceToolAssistantUUID": "130bd4cb-07fc-4964-9f03-cf47d354c42e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-18T12:24:56.358Z_

<details><summary>Logged reasoning block</summary>

```text
Good, I have the review form and found the tex files. Now let me read all the paper sections. Let me read them all in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6d7de2e4-3724-4207-8cc0-5b830f3645ed",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "66646abf-209f-4587-bdc6-be990fc6e40e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 24 · 2026-05-18T12:24:56.856Z_

已获取 ACL ARR 评分标准。现在通读论文全文。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "66646abf-209f-4587-bdc6-be990fc6e40e",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "314e82b6-f41d-4f9f-85a7-36bb2b2e51ef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 25 · 2026-05-18T12:24:57.861Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SMnj31tT6JbbBXhPwTo4Wo`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "314e82b6-f41d-4f9f-85a7-36bb2b2e51ef",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "e0d128aa-4722-4d31-9720-e23893809013",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 26 · 2026-05-18T12:25:02.305Z_

<details><summary>↩ Tool result · `toolu_012sr2Y6pMsob15zzbM2uUyu`</summary>

```text
1	\appendix
2	
3	\section{Inference Efficiency}
4	\label{app:latency}
5	
6	Table~\ref{tab:latency} reports inference throughput on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (batch size 1, sequence length 2048, fp16, averaged over 100 forward passes).
7	
8	\begin{table}[h]
9	\centering
10	\caption{Inference latency on LLaMA-3.1-8B (RTX PRO 6000 Blackwell, batch=1, seq=2048, fp16, 100 forward passes). Overhead is relative to dense inference.}
11	\label{tab:latency}
12	\small
13	\begin{tabular}{llcccc}
14	\toprule
15	Method & Sparsity & ms/fwd & tok/s & Overhead \\
16	\midrule
17	Dense & 0\% & 119.11$\pm$0.57 & 17{,}195 & --- \\
18	\midrule
19	KL predictor-only & 30\% & 126.64$\pm$0.70 & 16{,}172 & +6.3\% \\ % exp_id: latency_bench
20	KL predictor-only & 50\% & 126.78$\pm$0.31 & 16{,}154 & +6.4\% \\ % exp_id: latency_bench
21	\midrule
22	Predictor + compensation & 30\% & 129.94$\pm$0.75 & 15{,}761 & +9.1\% \\ % exp_id: latency_bench
23	Predictor + compensation & 50\% & 129.71$\pm$0.53 & 15{,}789 & +8.9\% \\ % exp_id: latency_bench
24	\bottomrule
25	\end{tabular}
26	\end{table}
27	
28	The full KL-sparse pipeline adds 6.4\% overhead to dense inference (126.78 vs.\ 119.11\,ms/forward), of which the predictor's 32-layer forward pass contributes 3.17\,ms (2.7\%); the remainder arises from mask application and sparse FFN indexing.
29	Eliminating the compensation network saves an additional $\sim$2.7\% latency overhead and 67.2M parameters (the per-layer GEMV required for output rescaling); KL distillation thus provides both quality and efficiency advantages over BCE-based approaches.
30	The overhead is near-identical at 30\% and 50\% sparsity because the predictor runs the same computation regardless of target sparsity; only the top-$k$ threshold changes.
31	
32	Note that the current implementation uses unstructured element-wise masks, which do not translate to wall-clock speedup without sparse kernel support.
33	The pipeline adds $\sim$6.4\% overhead; net acceleration requires kernel-level sparse computation optimizations (e.g., Triton block-sparse, cuSPARSE) that are beyond the scope of this work.
34	Our contribution is prediction quality and inference simplification (removing the compensation network), not end-to-end latency reduction.
35	
36	
37	\section{Predictor Bottleneck Sensitivity}
38	\label{app:db_sensitivity}
39	
40	Table~\ref{tab:db_sensitivity} reports the effect of predictor bottleneck dimension $d_b$ on PPL at 50\% sparsity under both TEAL global allocation (the paper's primary inference protocol) and per-token evaluation.
41	
42	\begin{table}[h]
43	\centering
44	\caption{Predictor bottleneck sensitivity at 50\% sparsity (WikiText-2 PPL$\downarrow$). TEAL global is the primary inference protocol; per-token shown for reference.}
45	\label{tab:db_sensitivity}
46	\small
47	\begin{tabular}{lcccc}
48	\toprule
49	$d_b$ & Params & TEAL global & $\Delta$ & Per-token \\
50	\midrule
51	64 & 38.2M (0.48\%) & 12.076 & +0.9\% & 10.16 \\ % exp_id: db_sensitivity_sweep
52	128 & 75.9M (0.95\%) & 11.963 & --- & 9.218 \\ % exp_id: db_sensitivity_sweep
53	256 & 151.5M (1.89\%) & 12.105 & +1.2\% & 8.586 \\ % exp_id: db_sensitivity_sweep
54	512 & 302.5M (3.77\%) & 12.315 & +2.9\% & 7.93 \\ % exp_id: db_sensitivity_sweep
55	\bottomrule
56	\end{tabular}
57	\end{table}
58	
59	Under TEAL global allocation, increasing $d_b$ beyond 128 provides no benefit (PPL slightly worsens), while per-token evaluation shows monotonic improvement (10.16$\to$7.93).
60	This divergence indicates that the global top-$k$ allocation mechanism, not predictor capacity, is the binding constraint: additional predictor capacity produces better per-neuron scores, but the global ranking and budget distribution cannot exploit them.
61	The $d_b{=}128$ configuration (75.9M params, $<$1\% of base model) is therefore optimal for the TEAL inference protocol.
62	
63	\subsection{Temperature Schedule Sensitivity}
64	\label{app:tau_sensitivity}
65	
66	\begin{table}[h]
67	\centering
68	\caption{Temperature schedule sensitivity at 50\% sparsity (WikiText-2 PPL$\downarrow$, TEAL global).}
69	\label{tab:tau_sensitivity}
70	\small
71	\begin{tabular}{lc}
72	\toprule
73	$\tau$ Schedule & PPL$\downarrow$ \\
74	\midrule
75	Fixed $\tau{=}0.5$ & \textbf{11.861} \\ % exp_id: tau_schedule_sweep
76	Linear $1.0 \to 0.1$ (default) & 11.963 \\ % exp_id: tau_schedule_sweep
77	Fixed $\tau{=}0.1$ & 12.072 \\ % exp_id: tau_schedule_sweep
78	\bottomrule
79	\end{tabular}
80	\end{table}
81	
82	Temperature schedule has minimal impact ($<$1.8\% PPL variation).
83	The linear annealing default is a conservative choice; even removing annealing entirely (fixed $\tau{=}0.5$) yields comparable performance.
84	
85	\subsection{Training Convergence}
86	\label{app:training_convergence}
87	
88	\begin{table}[h]
89	\centering
90	\caption{Training convergence at 50\% sparsity (WikiText-2 PPL$\downarrow$, TEAL global).}
91	\label{tab:training_convergence}
92	\small
93	\begin{tabular}{cc}
94	\toprule
95	Steps & PPL$\downarrow$ \\
96	\midrule
97	200 & 15.158 \\ % exp_id: training_steps_sweep
98	400 & 12.538 \\ % exp_id: training_steps_sweep
99	600 & 12.046 \\ % exp_id: training_steps_sweep
100	800 & 11.907 \\ % exp_id: training_steps_sweep
101	1000 & \textbf{11.906} \\ % exp_id: training_steps_sweep
102	\bottomrule
103	\end{tabular}
104	\end{table}
105	
106	Training converges rapidly: 95\% of the quality gap closes by step 600, and performance saturates by step 800 ($\Delta < 0.001$ between 800 and 1000 steps).
107	Our default of 1000 steps provides a conservative margin.
108	
109	
110	\section{Adaptive Penalty Controller Dynamics}
111	\label{app:lagrangian}
112	
113	Table~\ref{tab:lagrangian} reports the convergence of the adaptive penalty controller across sparsity targets.
114	The geometric doubling pattern ($1 \to 2 \to 4 \to 8 \to \ldots$) enables $\lambda$ to reach steady state within $\sim$10 steps; the deadzone ($\epsilon = 0.02$) then stabilizes $\lambda$ once actual sparsity is within $\pm$2\% of the target.
115	
116	\begin{table}[h]
117	\centering
118	\caption{Penalty controller convergence across sparsity targets (multiplicative schedule, margin $\epsilon=0.02$, 1000 training steps). Deviation is $|$actual $-$ target$|$ / target.}
119	\label{tab:lagrangian}
120	\small
121	\begin{tabular}{lccccc}
122	\toprule
123	Target $\rho$ & $\lambda_{\max}$ & Final $\lambda$ & Actual sparsity & Deviation \\
124	\midrule
125	30\% & 5000 & 5000 (cap) & 0.285 & 5.0\% \\ % exp_id: kl_30pct_s42
126	40\% & 5000 & 625 & 0.398 & 0.5\% \\ % exp_id: kl_40pct_s42
127	50\% & 1000 & 8 & 0.504 & 0.8\% \\ % exp_id: kl_50pct_s42
128	70\% & 1000 & 1000 (cap) & 0.688 & 1.7\% \\ % exp_id: kl_70pct_s42
129	\bottomrule
130	\end{tabular}
131	\end{table}
132	
133	At 50\% sparsity, the SwiGLU gate distribution already clusters near the target, so $\lambda$ remains low (8); the constraint is nearly satisfied by the initial predictor outputs.
134	At 30\% and 70\%, the gap between the gate prior and target is larger, driving $\lambda$ to its respective caps.
135	The 40\% target converges to $\lambda = 625$ with only 0.5\% deviation; this precision reflects a regime where the target is reachable without $\lambda$ saturation.
136	
137	\begin{figure}[h]
138	\centering
139	\includegraphics[width=\columnwidth]{lagrangian_dynamics.pdf}
140	\caption{Adaptive penalty controller convergence across sparsity targets. Upper panel: penalty weight $\lambda$ (log scale) over training steps. The 30\% target requires extreme penalty ($\lambda \to 5000$) to suppress activations below their natural density, while 50\% needs only $\lambda \approx 8$ since SwiGLU gates already cluster near this sparsity. Lower panel: actual sparsity (solid) converges to the target (dashed) within $\sim$10 steps via geometric doubling.}
141	\label{fig:lagrangian_dynamics}
142	\end{figure}
143	
144	Temperature $\tau$ is annealed linearly from 1.0 to 0.1 over 1000 steps.
145	A mild loss increase in the final $\sim$100 steps is expected: as masks become more binary ($\tau \to 0$), discrete rounding noise slightly increases KL divergence, consistent with convergence toward the hard-mask inference regime.
146	
147	The controller reliably drives actual sparsity to within 5\% of the target across all tested regimes, with $\lambda$ spanning three orders of magnitude (8 to 5000) via geometric doubling.
148	For the recommended 30\% operating point, actual sparsity is $\approx$28.5\% (5\% deviation). This does not affect conclusions: TEAL at interpolated 28.5\% actual sparsity yields PPL$\approx$10.7 (vs.\ 10.97 at exact 30\%), a $<$0.3 PPL difference negligible relative to the KL vs.\ TEAL gap (8.96 vs.\ 10.97).
149	
150	
151	\section{Out-of-Distribution Evaluation}
152	\label{app:ood}
153	
154	To address concerns about data homogeneity between training (WikiText-103) and evaluation (WikiText-2), we evaluate on C4~\cite{raffel2020c4} validation set under TEAL global allocation.
155	
156	\begin{table}[h]
157	\centering
158	\caption{Out-of-distribution evaluation on C4 validation (PPL$\downarrow$). 30\% KL reports 2-seed mean$\pm$std; other entries use seed 42.}
159	\label{tab:ood}
160	\small
161	\begin{tabular}{llc}
162	\toprule
163	Sparsity & Method & C4 PPL$\downarrow$ \\
164	\midrule
165	0\% & Dense & 9.21 \\
166	\midrule
167	30\% & KL predictor (Ours) & \textbf{16.03$\pm$0.01} \\ % exp_id: c4_ood_kl30_s42, c4_ood_kl30_s123
168	\midrule
169	\multirow{2}{*}{50\%} & KL predictor (Ours) & \textbf{18.40} \\ % exp_id: eval_c4_ood_kl50
170	& TEAL vanilla & 38.75 \\
171	\bottomrule
172	\end{tabular}
173	\end{table}
174	
175	At the recommended 30\% operating point, the KL predictor achieves C4 PPL 16.03$\pm$0.01 (2-seed, $1.74\times$ dense), confirming OOD generalization at the deployment-relevant sparsity level.
176	At 50\%, the KL predictor achieves 52.5\% relative advantage over TEAL (18.40 vs.\ 38.75), comparable to the 49\% advantage on WikiText-2 (11.79 vs.\ 23.31), confirming that KL-trained predictions generalize across distributions.
177	
178	
179	\section{Per-Layer Retention Analysis}
180	\label{app:retention}
181	
182	\begin{figure}[h]
183	\centering
184	\includegraphics[width=\columnwidth]{per_layer_retention_chart.pdf}
185	\caption{Per-layer neuron retention under global top-$k$ allocation at 30\%, 50\%, and 70\% sparsity. Dashed lines indicate uniform retention baselines. Late layers (L24--31) are consistently starved due to long-tailed activation distributions, with retention dropping to 28.4\% (L31) even at 30\% sparsity. At 70\%, starvation extends to mid-layers (L10--12: 16.7--20.1\%), explaining the transition to the capacity-limited regime.}
186	\label{fig:retention}
187	\end{figure}
188	
189	
190	\section{Training Stability}
191	\label{app:stability}
192	
193	Three-seed evaluation ($s \in \{42, 123, 456\}$) at 50\% sparsity under uniform allocation yields PPL $11.92 \pm 0.07$ (CV=0.6\%); training is stable across random initializations. % exp_id: multi_seed_kl50_uniform
194	Downstream metrics are similarly stable: ARC-c $33.8 \pm 1.2$\%, WinoGrande $62.9 \pm 0.1$\%, MMLU $28.0 \pm 0.6$\%, GSM8K $2.2 \pm 0.1$\%.
195	
196	Under global allocation at 50\%, MMLU is equally stable: $28.1 \pm 0.2$\% (s42=27.89, s123=28.34, s456=27.94); the near-random performance is therefore capacity-limited rather than seed-sensitive ($\sigma$=0.2pp vs.\ 9.5pp at 30\% global). % exp_id: multi_seed_kl50_global
197	The low standard deviation across both allocation strategies indicates that the KL training landscape is well-conditioned for this predictor architecture, with low sensitivity to initialization.
198	
199	
200	\section{Extended SNR Analysis}
201	\label{app:snr_extended}
202	
203	We measure per-layer gradient SNR at 7 checkpoints (steps 0, 50, 100, 150, 200, 250, 300) with 95\% bootstrap confidence intervals.
204	The SNR trajectory is non-monotonic: KL starts with higher SNR at step 0, but BCE surpasses KL during mid-training (steps 100--250) as its per-neuron classification objective concentrates gradients on the remaining hard neurons. KL's advantage re-emerges in later training and reaches $5.14\times$ at convergence (step 300: $5.877{\times}10^{-3}$ vs.\ $1.144{\times}10^{-3}$). % exp_id: snr_extended_r6w3
205	This reversal is consistent with KL's gradient coupling becoming effective only after the predictor has learned a coarse mask structure: early training explores broadly (lower SNR), while convergence concentrates signal through the inter-neuron Jacobian pathway (\S\ref{sec:method:gradient}).
206	
207	
208	\section{Extended Downstream Evaluation}
209	\label{app:downstream}
210	
211	Table~\ref{tab:downstream} compares Dense, KL 30\% (uniform allocation), and TEAL 30\% on three additional downstream benchmarks not included in the main results.
212	
213	\begin{table}[h]
214	\centering
215	\caption{Extended downstream benchmarks at 30\% sparsity (LLaMA-3.1-8B, seed 42). HellaSwag: 10-shot normalized acc; PIQA: 0-shot normalized acc; BoolQ: 0-shot acc.}
216	\label{tab:downstream}
217	\small
218	\begin{tabular}{lccc}
219	\toprule
220	Method & HellaSwag & PIQA & BoolQ \\
221	\midrule
222	Dense & \textbf{82.33} & \textbf{80.74} & \textbf{82.94} \\
223	KL 30\% uniform & 72.70 & 75.95 & 76.85 \\ % exp_id: downstream_extended_kl30_s42
224	TEAL 30\% vanilla & 66.70 & 73.61 & 68.50 \\ % exp_id: downstream_teal30_baseline
225	\bottomrule
226	\end{tabular}
227	\end{table}
228	
229	The KL predictor outperforms TEAL on all three benchmarks. On HellaSwag, it preserves 88.3\% of dense accuracy (72.70 vs.\ 82.33) vs.\ 81.0\% for TEAL (66.70). BoolQ shows the largest gap: 92.7\% vs.\ 82.6\% preservation. PIQA shows a smaller differential (94.1\% vs.\ 91.2\%).
230	
231	
232	\section{Compensation Training Convergence}
233	\label{app:comp_convergence}
234	
235	All compensation networks~\cite{gautam2026fastforward} were trained for 1000 steps (lr=$10^{-4}$, batch size 4, seq length 2048). Training loss plateaus by step 700 across all valid runs: 30\% s42 (final loss 0.70), 30\% s456 (0.68), 50\% s42 (1.07), with fluctuations remaining within 0.08 loss units for the final 300 steps. The compensation network converges but provides no quality improvement over the KL predictor alone, confirming that the redundancy result reflects predictor self-sufficiency rather than insufficient compensation training. % exp_id: kl_comp_30_s42, kl_comp_30_s456, kl_comp_50_s42
236	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "16514193-3cef-4483-82f3-9fff786a4267",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "19521a26-d77a-459a-b35c-0904a932a061",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/appendix.tex",
      "content": "\\appendix\n\n\\section{Inference Efficiency}\n\\label{app:latency}\n\nTable~\\ref{tab:latency} reports inference throughput on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (batch size 1, sequence length 2048, fp16, averaged over 100 forward passes).\n\n\\begin{table}[h]\n\\centering\n\\caption{Inference latency on LLaMA-3.1-8B (RTX PRO 6000 Blackwell, batch=1, seq=2048, fp16, 100 forward passes). Overhead is relative to dense inference.}\n\\label{tab:latency}\n\\small\n\\begin{tabular}{llcccc}\n\\toprule\nMethod & Sparsity & ms/fwd & tok/s & Overhead \\\\\n\\midrule\nDense & 0\\% & 119.11$\\pm$0.57 & 17{,}195 & --- \\\\\n\\midrule\nKL predictor-only & 30\\% & 126.64$\\pm$0.70 & 16{,}172 & +6.3\\% \\\\ % exp_id: latency_bench\nKL predictor-only & 50\\% & 126.78$\\pm$0.31 & 16{,}154 & +6.4\\% \\\\ % exp_id: latency_bench\n\\midrule\nPredictor + compensation & 30\\% & 129.94$\\pm$0.75 & 15{,}761 & +9.1\\% \\\\ % exp_id: latency_bench\nPredictor + compensation & 50\\% & 129.71$\\pm$0.53 & 15{,}789 & +8.9\\% \\\\ % exp_id: latency_bench\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe full KL-sparse pipeline adds 6.4\\% overhead to dense inference (126.78 vs.\\ 119.11\\,ms/forward), of which the predictor's 32-layer forward pass contributes 3.17\\,ms (2.7\\%); the remainder arises from mask application and sparse FFN indexing.\nEliminating the compensation network saves an additional $\\sim$2.7\\% latency overhead and 67.2M parameters (the per-layer GEMV required for output rescaling); KL distillation thus provides both quality and efficiency advantages over BCE-based approaches.\nThe overhead is near-identical at 30\\% and 50\\% sparsity because the predictor runs the same computation regardless of target sparsity; only the top-$k$ threshold changes.\n\nNote that the current implementation uses unstructured element-wise masks, which do not translate to wall-clock speedup without sparse kernel support.\nThe pipeline adds $\\sim$6.4\\% overhead; net acceleration requires kernel-level sparse computation optimizations (e.g., Triton block-sparse, cuSPARSE) that are beyond the scope of this work.\nOur contribution is prediction quality and inference simplification (removing the compensation network), not end-to-end latency reduction.\n\n\n\\section{Predictor Bottleneck Sensitivity}\n\\label{app:db_sensitivity}\n\nTable~\\ref{tab:db_sensitivity} reports the effect of predictor bottleneck dimension $d_b$ on PPL at 50\\% sparsity under both TEAL global allocation (the paper's primary inference protocol) and per-token evaluation.\n\n\\begin{table}[h]\n\\centering\n\\caption{Predictor bottleneck sensitivity at 50\\% sparsity (WikiText-2 PPL$\\downarrow$). TEAL global is the primary inference protocol; per-token shown for reference.}\n\\label{tab:db_sensitivity}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n$d_b$ & Params & TEAL global & $\\Delta$ & Per-token \\\\\n\\midrule\n64 & 38.2M (0.48\\%) & 12.076 & +0.9\\% & 10.16 \\\\ % exp_id: db_sensitivity_sweep\n128 & 75.9M (0.95\\%) & 11.963 & --- & 9.218 \\\\ % exp_id: db_sensitivity_sweep\n256 & 151.5M (1.89\\%) & 12.105 & +1.2\\% & 8.586 \\\\ % exp_id: db_sensitivity_sweep\n512 & 302.5M (3.77\\%) & 12.315 & +2.9\\% & 7.93 \\\\ % exp_id: db_sensitivity_sweep\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nUnder TEAL global allocation, increasing $d_b$ beyond 128 provides no benefit (PPL slightly worsens), while per-token evaluation shows monotonic improvement (10.16$\\to$7.93).\nThis divergence indicates that the global top-$k$ allocation mechanism, not predictor capacity, is the binding constraint: additional predictor capacity produces better per-neuron scores, but the global ranking and budget distribution cannot exploit them.\nThe $d_b{=}128$ configuration (75.9M params, $<$1\\% of base model) is therefore optimal for the TEAL inference protocol.\n\n\\subsection{Temperature Schedule Sensitivity}\n\\label{app:tau_sensitivity}\n\n\\begin{table}[h]\n\\centering\n\\caption{Temperature schedule sensitivity at 50\\% sparsity (WikiText-2 PPL$\\downarrow$, TEAL global).}\n\\label{tab:tau_sensitivity}\n\\small\n\\begin{tabular}{lc}\n\\toprule\n$\\tau$ Schedule & PPL$\\downarrow$ \\\\\n\\midrule\nFixed $\\tau{=}0.5$ & \\textbf{11.861} \\\\ % exp_id: tau_schedule_sweep\nLinear $1.0 \\to 0.1$ (default) & 11.963 \\\\ % exp_id: tau_schedule_sweep\nFixed $\\tau{=}0.1$ & 12.072 \\\\ % exp_id: tau_schedule_sweep\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTemperature schedule has minimal impact ($<$1.8\\% PPL variation).\nThe linear annealing default is a conservative choice; even removing annealing entirely (fixed $\\tau{=}0.5$) yields comparable performance.\n\n\\subsection{Training Convergence}\n\\label{app:training_convergence}\n\n\\begin{table}[h]\n\\centering\n\\caption{Training convergence at 50\\% sparsity (WikiText-2 PPL$\\downarrow$, TEAL global).}\n\\label{tab:training_convergence}\n\\small\n\\begin{tabular}{cc}\n\\toprule\nSteps & PPL$\\downarrow$ \\\\\n\\midrule\n200 & 15.158 \\\\ % exp_id: training_steps_sweep\n400 & 12.538 \\\\ % exp_id: training_steps_sweep\n600 & 12.046 \\\\ % exp_id: training_steps_sweep\n800 & 11.907 \\\\ % exp_id: training_steps_sweep\n1000 & \\textbf{11.906} \\\\ % exp_id: training_steps_sweep\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTraining converges rapidly: 95\\% of the quality gap closes by step 600, and performance saturates by step 800 ($\\Delta < 0.001$ between 800 and 1000 steps).\nOur default of 1000 steps provides a conservative margin.\n\n\n\\section{Adaptive Penalty Controller Dynamics}\n\\label{app:lagrangian}\n\nTable~\\ref{tab:lagrangian} reports the convergence of the adaptive penalty controller across sparsity targets.\nThe geometric doubling pattern ($1 \\to 2 \\to 4 \\to 8 \\to \\ldots$) enables $\\lambda$ to reach steady state within $\\sim$10 steps; the deadzone ($\\epsilon = 0.02$) then stabilizes $\\lambda$ once actual sparsity is within $\\pm$2\\% of the target.\n\n\\begin{table}[h]\n\\centering\n\\caption{Penalty controller convergence across sparsity targets (multiplicative schedule, margin $\\epsilon=0.02$, 1000 training steps). Deviation is $|$actual $-$ target$|$ / target.}\n\\label{tab:lagrangian}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nTarget $\\rho$ & $\\lambda_{\\max}$ & Final $\\lambda$ & Actual sparsity & Deviation \\\\\n\\midrule\n30\\% & 5000 & 5000 (cap) & 0.285 & 5.0\\% \\\\ % exp_id: kl_30pct_s42\n40\\% & 5000 & 625 & 0.398 & 0.5\\% \\\\ % exp_id: kl_40pct_s42\n50\\% & 1000 & 8 & 0.504 & 0.8\\% \\\\ % exp_id: kl_50pct_s42\n70\\% & 1000 & 1000 (cap) & 0.688 & 1.7\\% \\\\ % exp_id: kl_70pct_s42\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt 50\\% sparsity, the SwiGLU gate distribution already clusters near the target, so $\\lambda$ remains low (8); the constraint is nearly satisfied by the initial predictor outputs.\nAt 30\\% and 70\\%, the gap between the gate prior and target is larger, driving $\\lambda$ to its respective caps.\nThe 40\\% target converges to $\\lambda = 625$ with only 0.5\\% deviation; this precision reflects a regime where the target is reachable without $\\lambda$ saturation.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{lagrangian_dynamics.pdf}\n\\caption{Adaptive penalty controller convergence across sparsity targets. Upper panel: penalty weight $\\lambda$ (log scale) over training steps. The 30\\% target requires extreme penalty ($\\lambda \\to 5000$) to suppress activations below their natural density, while 50\\% needs only $\\lambda \\approx 8$ since SwiGLU gates already cluster near this sparsity. Lower panel: actual sparsity (solid) converges to the target (dashed) within $\\sim$10 steps via geometric doubling.}\n\\label{fig:lagrangian_dynamics}\n\\end{figure}\n\nTemperature $\\tau$ is annealed linearly from 1.0 to 0.1 over 1000 steps.\nA mild loss increase in the final $\\sim$100 steps is expected: as masks become more binary ($\\tau \\to 0$), discrete rounding noise slightly increases KL divergence, consistent with convergence toward the hard-mask inference regime.\n\nThe controller reliably drives actual sparsity to within 5\\% of the target across all tested regimes, with $\\lambda$ spanning three orders of magnitude (8 to 5000) via geometric doubling.\nFor the recommended 30\\% operating point, actual sparsity is $\\approx$28.5\\% (5\\% deviation). This does not affect conclusions: TEAL at interpolated 28.5\\% actual sparsity yields PPL$\\approx$10.7 (vs.\\ 10.97 at exact 30\\%), a $<$0.3 PPL difference negligible relative to the KL vs.\\ TEAL gap (8.96 vs.\\ 10.97).\n\n\n\\section{Out-of-Distribution Evaluation}\n\\label{app:ood}\n\nTo address concerns about data homogeneity between training (WikiText-103) and evaluation (WikiText-2), we evaluate on C4~\\cite{raffel2020c4} validation set under TEAL global allocation.\n\n\\begin{table}[h]\n\\centering\n\\caption{Out-of-distribution evaluation on C4 validation (PPL$\\downarrow$). 30\\% KL reports 2-seed mean$\\pm$std; other entries use seed 42.}\n\\label{tab:ood}\n\\small\n\\begin{tabular}{llc}\n\\toprule\nSparsity & Method & C4 PPL$\\downarrow$ \\\\\n\\midrule\n0\\% & Dense & 9.21 \\\\\n\\midrule\n30\\% & KL predictor (Ours) & \\textbf{16.03$\\pm$0.01} \\\\ % exp_id: c4_ood_kl30_s42, c4_ood_kl30_s123\n\\midrule\n\\multirow{2}{*}{50\\%} & KL predictor (Ours) & \\textbf{18.40} \\\\ % exp_id: eval_c4_ood_kl50\n& TEAL vanilla & 38.75 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt the recommended 30\\% operating point, the KL predictor achieves C4 PPL 16.03$\\pm$0.01 (2-seed, $1.74\\times$ dense), confirming OOD generalization at the deployment-relevant sparsity level.\nAt 50\\%, the KL predictor achieves 52.5\\% relative advantage over TEAL (18.40 vs.\\ 38.75), comparable to the 49\\% advantage on WikiText-2 (11.79 vs.\\ 23.31), confirming that KL-trained predictions generalize across distributions.\n\n\n\\section{Per-Layer Retention Analysis}\n\\label{app:retention}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{per_layer_retention_chart.pdf}\n\\caption{Per-layer neuron retention under global top-$k$ allocation at 30\\%, 50\\%, and 70\\% sparsity. Dashed lines indicate uniform retention baselines. Late layers (L24--31) are consistently starved due to long-tailed activation distributions, with retention dropping to 28.4\\% (L31) even at 30\\% sparsity. At 70\\%, starvation extends to mid-layers (L10--12: 16.7--20.1\\%), explaining the transition to the capacity-limited regime.}\n\\label{fig:retention}\n\\end{figure}\n\n\n\\section{Training Stability}\n\\label{app:stability}\n\nThree-seed evaluation ($s \\in \\{42, 123, 456\\}$) at 50\\% sparsity under uniform allocation yields PPL $11.92 \\pm 0.07$ (CV=0.6\\%); training is stable across random initializations. % exp_id: multi_seed_kl50_uniform\nDownstream metrics are similarly stable: ARC-c $33.8 \\pm 1.2$\\%, WinoGrande $62.9 \\pm 0.1$\\%, MMLU $28.0 \\pm 0.6$\\%, GSM8K $2.2 \\pm 0.1$\\%.\n\nUnder global allocation at 50\\%, MMLU is equally stable: $28.1 \\pm 0.2$\\% (s42=27.89, s123=28.34, s456=27.94); the near-random performance is therefore capacity-limited rather than seed-sensitive ($\\sigma$=0.2pp vs.\\ 9.5pp at 30\\% global). % exp_id: multi_seed_kl50_global\nThe low standard deviation across both allocation strategies indicates that the KL training landscape is well-conditioned for this predictor architecture, with low sensitivity to initialization.\n\n\n\\section{Extended SNR Analysis}\n\\label{app:snr_extended}\n\nWe measure per-layer gradient SNR at 7 checkpoints (steps 0, 50, 100, 150, 200, 250, 300) with 95\\% bootstrap confidence intervals.\nThe SNR trajectory is non-monotonic: KL starts with higher SNR at step 0, but BCE surpasses KL during mid-training (steps 100--250) as its per-neuron classification objective concentrates gradients on the remaining hard neurons. KL's advantage re-emerges in later training and reaches $5.14\\times$ at convergence (step 300: $5.877{\\times}10^{-3}$ vs.\\ $1.144{\\times}10^{-3}$). % exp_id: snr_extended_r6w3\nThis reversal is consistent with KL's gradient coupling becoming effective only after the predictor has learned a coarse mask structure: early training explores broadly (lower SNR), while convergence concentrates signal through the inter-neuron Jacobian pathway (\\S\\ref{sec:method:gradient}).\n\n\n\\section{Extended Downstream Evaluation}\n\\label{app:downstream}\n\nTable~\\ref{tab:downstream} compares Dense, KL 30\\% (uniform allocation), and TEAL 30\\% on three additional downstream benchmarks not included in the main results.\n\n\\begin{table}[h]\n\\centering\n\\caption{Extended downstream benchmarks at 30\\% sparsity (LLaMA-3.1-8B, seed 42). HellaSwag: 10-shot normalized acc; PIQA: 0-shot normalized acc; BoolQ: 0-shot acc.}\n\\label{tab:downstream}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nMethod & HellaSwag & PIQA & BoolQ \\\\\n\\midrule\nDense & \\textbf{82.33} & \\textbf{80.74} & \\textbf{82.94} \\\\\nKL 30\\% uniform & 72.70 & 75.95 & 76.85 \\\\ % exp_id: downstream_extended_kl30_s42\nTEAL 30\\% vanilla & 66.70 & 73.61 & 68.50 \\\\ % exp_id: downstream_teal30_baseline\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe KL predictor outperforms TEAL on all three benchmarks. On HellaSwag, it preserves 88.3\\% of dense accuracy (72.70 vs.\\ 82.33) vs.\\ 81.0\\% for TEAL (66.70). BoolQ shows the largest gap: 92.7\\% vs.\\ 82.6\\% preservation. PIQA shows a smaller differential (94.1\\% vs.\\ 91.2\\%).\n\n\n\\section{Compensation Training Convergence}\n\\label{app:comp_convergence}\n\nAll compensation networks~\\cite{gautam2026fastforward} were trained for 1000 steps (lr=$10^{-4}$, batch size 4, seq length 2048). Training loss plateaus by step 700 across all valid runs: 30\\% s42 (final loss 0.70), 30\\% s456 (0.68), 50\\% s42 (1.07), with fluctuations remaining within 0.08 loss units for the final 300 steps. The compensation network converges but provides no quality improvement over the KL predictor alone, confirming that the redundancy result reflects predictor self-sufficiency rather than insufficient compensation training. % exp_id: kl_comp_30_s42, kl_comp_30_s456, kl_comp_50_s42\n",
      "numLines": 236,
      "startLine": 1,
      "totalLines": 236
    }
  },
  "sourceToolAssistantUUID": "16514193-3cef-4483-82f3-9fff786a4267",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-18T12:24:57.871Z_

<details><summary>↩ Tool result · `toolu_01SMnj31tT6JbbBXhPwTo4Wo`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	% \usepackage{inconsolata} % not available on this system
9	\usepackage{graphicx}
10	\graphicspath{{../figures/paper/}}
11	\usepackage{amsmath}
12	\usepackage{amssymb}
13	\usepackage{booktabs}
14	\usepackage{multirow}
15	\usepackage{enumitem}
16	
17	\title{Output-Distribution Distillation for Contextual Sparsity Prediction in SwiGLU LLMs}
18	
19	\author{Anonymous}
20	
21	\begin{document}
22	\maketitle
23	
24	\begin{abstract}
25	\input{abstract}
26	\end{abstract}
27	
28	\input{introduction}
29	\input{related_work}
30	\input{method}
31	\input{experiments}
32	\input{conclusion}
33	\input{limitations}
34	\input{ethics}
35	
36	\bibliography{references}
37	
38	\input{appendix}
39	
40	\end{document}
41	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e0d128aa-4722-4d31-9720-e23893809013",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "9662864f-36d8-4586-9343-5e391114b976",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n% \\usepackage{inconsolata} % not available on this system\n\\usepackage{graphicx}\n\\graphicspath{{../figures/paper/}}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{booktabs}\n\\usepackage{multirow}\n\\usepackage{enumitem}\n\n\\title{Output-Distribution Distillation for Contextual Sparsity Prediction in SwiGLU LLMs}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\begin{abstract}\n\\input{abstract}\n\\end{abstract}\n\n\\input{introduction}\n\\input{related_work}\n\\input{method}\n\\input{experiments}\n\\input{conclusion}\n\\input{limitations}\n\\input{ethics}\n\n\\bibliography{references}\n\n\\input{appendix}\n\n\\end{document}\n",
      "numLines": 41,
      "startLine": 1,
      "totalLines": 41
    }
  },
  "sourceToolAssistantUUID": "e0d128aa-4722-4d31-9720-e23893809013",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-18T12:24:58.342Z_

<details open><summary>🔧 Tool call — Read · `toolu_01QwkzwsbGkeRzWHvNPXo5pR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9662864f-36d8-4586-9343-5e391114b976",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "12f50a01-304e-4ffa-9ec7-70052a15c4b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 29 · 2026-05-18T12:24:58.347Z_

<details><summary>↩ Tool result · `toolu_01QwkzwsbGkeRzWHvNPXo5pR`</summary>

```text
1	We study whether end-to-end KL distillation can replace per-neuron classification for activation sparsity prediction in SwiGLU LLMs.
2	Existing predictors trained with binary cross-entropy (BCE) optimize each neuron independently, but inference allocates sparsity budgets via global top-$k$ across all layers.
3	Gradient analysis reveals a structural mismatch: BCE's per-neuron gradient is blind to cross-neuron interactions and achieves higher oracle F1 yet 139\% worse perplexity than a KL-trained predictor.
4	A lightweight predictor ($<$1\% of base parameters) trained with forward KL and Gumbel-Sigmoid relaxation resolves this mismatch by coupling all neurons through the output distribution, rendering post-hoc compensation (+67.2M params) redundant at both 30\% and 50\% sparsity.
5	On LLaMA-3.1-8B at the recommended 30\% sparsity, KL reduces PPL degradation 18\% over TEAL; uniform allocation provides $7.5\times$ smaller cross-seed downstream $\sigma$, eliminating seed-dependent instability.
6	At 50\% sparsity, the PPL advantage widens to 49\% but downstream tasks degrade regardless of allocation, revealing allocation-dependent operating regions at 7--8B scale.
7	Evaluation on Mistral-7B-v0.3 and Qwen-2.5-14B confirms the PPL advantage across 7--14B, though 14B reveals a scale-dependent MMLU gap not resolved by allocation strategy.
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "12f50a01-304e-4ffa-9ec7-70052a15c4b2",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "761bbcaa-c33e-43d3-8f62-17c0454bc616",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/abstract.tex",
      "content": "We study whether end-to-end KL distillation can replace per-neuron classification for activation sparsity prediction in SwiGLU LLMs.\nExisting predictors trained with binary cross-entropy (BCE) optimize each neuron independently, but inference allocates sparsity budgets via global top-$k$ across all layers.\nGradient analysis reveals a structural mismatch: BCE's per-neuron gradient is blind to cross-neuron interactions and achieves higher oracle F1 yet 139\\% worse perplexity than a KL-trained predictor.\nA lightweight predictor ($<$1\\% of base parameters) trained with forward KL and Gumbel-Sigmoid relaxation resolves this mismatch by coupling all neurons through the output distribution, rendering post-hoc compensation (+67.2M params) redundant at both 30\\% and 50\\% sparsity.\nOn LLaMA-3.1-8B at the recommended 30\\% sparsity, KL reduces PPL degradation 18\\% over TEAL; uniform allocation provides $7.5\\times$ smaller cross-seed downstream $\\sigma$, eliminating seed-dependent instability.\nAt 50\\% sparsity, the PPL advantage widens to 49\\% but downstream tasks degrade regardless of allocation, revealing allocation-dependent operating regions at 7--8B scale.\nEvaluation on Mistral-7B-v0.3 and Qwen-2.5-14B confirms the PPL advantage across 7--14B, though 14B reveals a scale-dependent MMLU gap not resolved by allocation strategy.\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "12f50a01-304e-4ffa-9ec7-70052a15c4b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-18T12:24:58.820Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DSim3Wz58BmLFAs7DwZQyq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "761bbcaa-c33e-43d3-8f62-17c0454bc616",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "90ecbfbd-181a-4f4a-a0f4-4de9b3a60331",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 31 · 2026-05-18T12:24:58.825Z_

<details><summary>↩ Tool result · `toolu_01DSim3Wz58BmLFAs7DwZQyq`</summary>

```text
1	\section{Introduction}
2	
3	SwiGLU feed-forward networks~\cite{shazeer2020glu} in modern LLMs exhibit high contextual sparsity: at any given token, a large fraction of FFN neurons contribute negligibly to the output.
4	Learned sparsity predictors~\cite{liu2023dejavu,gautam2026fastforward} exploit this property by training small networks to anticipate which neurons are important, but they universally rely on binary cross-entropy (BCE) loss, treating each neuron as an independent classification target.
5	Yet at inference, sparsity budgets are allocated globally: TEAL's top-$k$ mechanism~\cite{liu2025teal} ranks all neurons across all layers and retains only those above a model-wide threshold.
6	This mismatch between per-neuron training and global inference allocation has not been formally analyzed.
7	
8	We provide this analysis.
9	The gradient of BCE with respect to neuron $j$'s score is $\partial \mathcal{L}_{\text{BCE}} / \partial s_j = \sigma(s_j) - m_j^*$, a function of $j$ alone, independent of every other neuron.
10	Under KL divergence, the gradient for neuron $j$ in layer $\ell$ factors as:
11	\begin{equation*}
12	\frac{\partial \mathcal{L}_{\text{KL}}}{\partial s_j^{(\ell)}} = \frac{\partial \mathcal{L}_{\text{KL}}}{\partial \mathbf{z}} \cdot \frac{\partial \mathbf{z}}{\partial \mathbf{h}^{(\ell)}} \cdot \frac{\partial \mathbf{h}^{(\ell)}}{\partial \tilde{m}_j^{(\ell)}} \cdot \frac{\partial \tilde{m}_j^{(\ell)}}{\partial s_j^{(\ell)}},
13	\end{equation*}
14	where the Jacobian $\partial \mathbf{z} / \partial \mathbf{h}^{(\ell)}$ propagates through all downstream layers, coupling each neuron's gradient to every other neuron's mask state.
15	This structural difference predicts that KL should outperform BCE specifically under global allocation, and the prediction is confirmed empirically: BCE achieves higher oracle F1 (0.613 vs.\ 0.540) yet produces 139\% worse perplexity, because per-neuron magnitude accuracy is a misaligned proxy for output-distribution preservation.
16	
17	To test whether end-to-end distillation can overcome this mismatch, we instantiate a lightweight predictor (75.9M params, $<$1\% of base) trained with forward KL and Gumbel-Sigmoid relaxation~\cite{jang2017gumbel} on LLaMA-3.1-8B~\cite{grattafiori2024llama3}.
18	With uniform allocation, the predictor achieves PPL 11.96 at 50\% sparsity; under global top-$k$, PPL improves to 11.79 (49\% over TEAL).
19	At the recommended 30\% operating point, global top-$k$ amplifies cross-seed downstream standard deviation ($7.5\times$), motivating uniform allocation for deployment.
20	Evaluation on Mistral-7B-v0.3~\cite{jiang2023mistral} and Qwen-2.5-14B~\cite{qwen2024qwen25} confirms the PPL advantage at 7--14B, with scale-dependent downstream effects at 14B.
21	
22	Our contributions are:
23	\begin{itemize}[nosep,leftmargin=*]
24	\item Empirical observation and quantification of the structural mismatch between per-neuron BCE training and global top-$k$ inference allocation, supported by oracle F1 decomposition and gradient SNR measurements (\S\ref{sec:method:gradient}).
25	\item Empirical validation that KL distillation overcomes this mismatch for activation sparsity: oracle F1 and perplexity are inversely decoupled, with BCE at +7pp F1 yet 139\% worse PPL; the resulting predictor renders post-hoc compensation redundant at both tested sparsity levels (\S\ref{sec:isocompute}).
26	\item Analysis of allocation-to-downstream interactions at 7--14B: late-layer starvation at 8B and scale-dependent effects at 14B (\S\ref{sec:scaling}).
27	\end{itemize}
28	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "90ecbfbd-181a-4f4a-a0f4-4de9b3a60331",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "1bfe3b50-2c0e-4ff0-8136-95d007badaf7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/introduction.tex",
      "content": "\\section{Introduction}\n\nSwiGLU feed-forward networks~\\cite{shazeer2020glu} in modern LLMs exhibit high contextual sparsity: at any given token, a large fraction of FFN neurons contribute negligibly to the output.\nLearned sparsity predictors~\\cite{liu2023dejavu,gautam2026fastforward} exploit this property by training small networks to anticipate which neurons are important, but they universally rely on binary cross-entropy (BCE) loss, treating each neuron as an independent classification target.\nYet at inference, sparsity budgets are allocated globally: TEAL's top-$k$ mechanism~\\cite{liu2025teal} ranks all neurons across all layers and retains only those above a model-wide threshold.\nThis mismatch between per-neuron training and global inference allocation has not been formally analyzed.\n\nWe provide this analysis.\nThe gradient of BCE with respect to neuron $j$'s score is $\\partial \\mathcal{L}_{\\text{BCE}} / \\partial s_j = \\sigma(s_j) - m_j^*$, a function of $j$ alone, independent of every other neuron.\nUnder KL divergence, the gradient for neuron $j$ in layer $\\ell$ factors as:\n\\begin{equation*}\n\\frac{\\partial \\mathcal{L}_{\\text{KL}}}{\\partial s_j^{(\\ell)}} = \\frac{\\partial \\mathcal{L}_{\\text{KL}}}{\\partial \\mathbf{z}} \\cdot \\frac{\\partial \\mathbf{z}}{\\partial \\mathbf{h}^{(\\ell)}} \\cdot \\frac{\\partial \\mathbf{h}^{(\\ell)}}{\\partial \\tilde{m}_j^{(\\ell)}} \\cdot \\frac{\\partial \\tilde{m}_j^{(\\ell)}}{\\partial s_j^{(\\ell)}},\n\\end{equation*}\nwhere the Jacobian $\\partial \\mathbf{z} / \\partial \\mathbf{h}^{(\\ell)}$ propagates through all downstream layers, coupling each neuron's gradient to every other neuron's mask state.\nThis structural difference predicts that KL should outperform BCE specifically under global allocation, and the prediction is confirmed empirically: BCE achieves higher oracle F1 (0.613 vs.\\ 0.540) yet produces 139\\% worse perplexity, because per-neuron magnitude accuracy is a misaligned proxy for output-distribution preservation.\n\nTo test whether end-to-end distillation can overcome this mismatch, we instantiate a lightweight predictor (75.9M params, $<$1\\% of base) trained with forward KL and Gumbel-Sigmoid relaxation~\\cite{jang2017gumbel} on LLaMA-3.1-8B~\\cite{grattafiori2024llama3}.\nWith uniform allocation, the predictor achieves PPL 11.96 at 50\\% sparsity; under global top-$k$, PPL improves to 11.79 (49\\% over TEAL).\nAt the recommended 30\\% operating point, global top-$k$ amplifies cross-seed downstream standard deviation ($7.5\\times$), motivating uniform allocation for deployment.\nEvaluation on Mistral-7B-v0.3~\\cite{jiang2023mistral} and Qwen-2.5-14B~\\cite{qwen2024qwen25} confirms the PPL advantage at 7--14B, with scale-dependent downstream effects at 14B.\n\nOur contributions are:\n\\begin{itemize}[nosep,leftmargin=*]\n\\item Empirical observation and quantification of the structural mismatch between per-neuron BCE training and global top-$k$ inference allocation, supported by oracle F1 decomposition and gradient SNR measurements (\\S\\ref{sec:method:gradient}).\n\\item Empirical validation that KL distillation overcomes this mismatch for activation sparsity: oracle F1 and perplexity are inversely decoupled, with BCE at +7pp F1 yet 139\\% worse PPL; the resulting predictor renders post-hoc compensation redundant at both tested sparsity levels (\\S\\ref{sec:isocompute}).\n\\item Analysis of allocation-to-downstream interactions at 7--14B: late-layer starvation at 8B and scale-dependent effects at 14B (\\S\\ref{sec:scaling}).\n\\end{itemize}\n",
      "numLines": 28,
      "startLine": 1,
      "totalLines": 28
    }
  },
  "sourceToolAssistantUUID": "90ecbfbd-181a-4f4a-a0f4-4de9b3a60331",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-18T12:24:59.298Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CV5yLc3uqy4zkBLThA4HZp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1bfe3b50-2c0e-4ff0-8136-95d007badaf7",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "9f09322b-91a8-46ed-87ce-b3f6b3144ac9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 33 · 2026-05-18T12:24:59.304Z_

<details><summary>↩ Tool result · `toolu_01CV5yLc3uqy4zkBLThA4HZp`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	We present a KL distillation framework for training contextual sparsity predictors in SwiGLU-based language models.
5	The method replaces per-neuron binary classification (BCE) with an output-distribution objective that couples all pruning decisions through the model's forward pass and achieves competitive performance without auxiliary error compensation networks at inference.
6	
7	\subsection{Problem Formulation}
8	\label{sec:method:formulation}
9	
10	Consider a pretrained transformer with $L$ layers, each containing a SwiGLU feed-forward network~\cite{shazeer2020glu}.
11	For layer $\ell$, the FFN computes:
12	\begin{align}
13	\mathbf{y}^{(\ell)} = \bigl(\sigma(\mathbf{x}^{(\ell)} \mathbf{W}_g^{(\ell)}) \odot \mathbf{x}^{(\ell)} \mathbf{W}_u^{(\ell)}\bigr) \mathbf{W}_d^{(\ell)},
14	\label{eq:swiglu}
15	\end{align}
16	where $\mathbf{x}^{(\ell)} \in \mathbb{R}^{d}$ is the hidden state after attention ($d{=}4096$), $\sigma$ denotes SiLU, $\mathbf{W}_g^{(\ell)}, \mathbf{W}_u^{(\ell)} \in \mathbb{R}^{d \times d_{\text{ff}}}$ and $\mathbf{W}_d^{(\ell)} \in \mathbb{R}^{d_{\text{ff}} \times d}$ are the gate, up-projection, and down-projection matrices, and $d_{\text{ff}}{=}14{,}336$.
17	
18	Define the gate activation $\mathbf{g}^{(\ell)} = \sigma(\mathbf{x}^{(\ell)} \mathbf{W}_g^{(\ell)}) \in \mathbb{R}^{d_{\text{ff}}}$.
19	Each element $g_j^{(\ell)}$ determines the contribution of neuron $j$ to the output.
20	We introduce a binary mask $\mathbf{m}^{(\ell)} \in \{0,1\}^{d_{\text{ff}}}$ that zeros out pruned neurons:
21	\begin{align}
22	\mathbf{y}_{\text{sparse}}^{(\ell)} = \bigl(\mathbf{m}^{(\ell)} \odot \mathbf{g}^{(\ell)} \odot \mathbf{x}^{(\ell)} \mathbf{W}_u^{(\ell)}\bigr) \mathbf{W}_d^{(\ell)}.
23	\label{eq:sparse_ffn}
24	\end{align}
25	Our goal is to learn a mask predictor $f_\theta^{(\ell)}(\mathbf{h}) \to \mathbf{s}^{(\ell)} \in (0,1)^{d_{\text{ff}}}$ that produces per-neuron importance scores from the pre-FFN hidden state $\mathbf{h}$.
26	At inference, the scores are fed to a global top-$k$ allocation mechanism~\cite{liu2025teal} that distributes the sparsity budget across layers non-uniformly, retaining the $(1{-}\rho) \times L \times d_{\text{ff}}$ highest-scoring neurons model-wide for a target sparsity ratio $\rho$.
27	
28	
29	\subsection{Predictor Architecture}
30	\label{sec:method:predictor}
31	
32	Each layer $\ell$ has an independent two-layer MLP predictor:
33	\begin{align}
34	f_\theta^{(\ell)}(\mathbf{h}) = \text{GELU}(\mathbf{h} \mathbf{W}_1^{(\ell)}) \, \mathbf{W}_2^{(\ell)},
35	\label{eq:predictor}
36	\end{align}
37	where $\mathbf{W}_1^{(\ell)} \in \mathbb{R}^{d \times d_b}$ and $\mathbf{W}_2^{(\ell)} \in \mathbb{R}^{d_b \times d_{\text{ff}}}$ with bottleneck dimension $d_b{=}128$.
38	The predictor takes the hidden state after attention (before the FFN) and outputs $d_{\text{ff}}$-dimensional logits $\mathbf{s}^{(\ell)}$, from which the mask is derived.
39	
40	Each predictor has $(4096 \times 128) + (128 \times 14336) = 2.37\text{M}$ parameters.
41	With 32 independent predictors (one per layer), the total overhead is 75.9M parameters, less than 1\% of the 8B base model.
42	The predictors operate independently across layers, requiring no cross-layer communication at inference.
43	
44	
45	\subsection{Gumbel-Sigmoid Relaxation}
46	\label{sec:method:gumbel}
47	
48	The hard mask $m_j = \mathbf{1}[s_j > \text{threshold}]$ is non-differentiable, preventing gradient flow from the KL objective through the mask to the predictor parameters.
49	We apply Gumbel-Sigmoid relaxation~\cite{jang2017gumbel} to produce differentiable soft masks:
50	\begin{align}
51	\tilde{m}_j = \sigma_\tau\!\left(\log \frac{s_j}{1 - s_j} + g_1 - g_2\right), \quad g_1, g_2 \sim \text{Gumbel}(0,1),
52	\label{eq:gumbel}
53	\end{align}
54	where $\sigma_\tau(x) = \text{sigmoid}(x / \tau)$ and $\tau$ is a temperature parameter.
55	The Gumbel noise provides stochastic exploration of mask configurations during training, while the temperature controls sharpness: as $\tau \to 0$, $\tilde{m}_j$ approaches a binary decision.
56	
57	We anneal $\tau$ linearly from 1.0 to 0.1 over training.
58	At high temperature, the soft mask permits gradient flow through all neurons for broad exploration.
59	As temperature decreases, the mask concentrates on confident decisions, approximating the hard allocation used at inference.
60	
61	\paragraph{Comparison with Straight-Through Estimation.}
62	The straight-through estimator (STE)~\cite{bengio2013ste} applies a hard threshold in the forward pass and passes gradients through unchanged ($\partial m / \partial s = 1$).
63	In our setting, STE produces discontinuous gradient signals: small parameter changes can flip many neurons simultaneously, causing violent oscillations in the penalty weight and failure to converge to the target sparsity.
64	Gumbel relaxation eliminates this pathology, contributing a 34.5\% improvement (PPL 15.77 $\to$ 11.79 at 50\% sparsity), as we verify empirically in \S\ref{sec:experiments}.
65	
66	
67	\subsection{KL Divergence Training Objective}
68	\label{sec:method:kl}
69	
70	Let $\mathbf{z}_{\text{dense}}$ denote the output logits from a full dense forward pass, and $\mathbf{z}_{\text{sparse}}$ the logits from a forward pass with predictor-generated soft masks $\{\tilde{\mathbf{m}}^{(\ell)}\}_\ell$ applied at every layer.
71	We minimize the forward KL divergence between the dense and sparse output distributions:
72	\begin{align}
73	\mathcal{L}_{\text{KL}} = D_{\text{KL}}(p_{\text{dense}} \,\|\, p_{\text{sparse}}) = \sum_{v} p_{\text{dense}}^{(v)} \log \frac{p_{\text{dense}}^{(v)}}{p_{\text{sparse}}^{(v)}},
74	\label{eq:kl_loss}
75	\end{align}
76	where $p_{\text{dense}} = \text{softmax}(\mathbf{z}_{\text{dense}})$ and $p_{\text{sparse}} = \text{softmax}(\mathbf{z}_{\text{sparse}})$, summed over the vocabulary $v$ and averaged over sequence positions.
77	The base model is frozen; only the predictor parameters receive gradients.
78	
79	We use forward KL (mean-seeking) rather than reverse KL, as the goal is to preserve the dense model's primary predictions rather than explore alternative modes; \S\ref{sec:experiments} validates this choice with ablations over divergence direction (forward KL outperforms JSD by 6.4\% and reverse KL by 8.6\%).
80	No temperature scaling ($T{=}1$) is applied~\cite{hinton2015distilling}.
81	
82	
83	\subsection{Adaptive Penalty Sparsity Controller}
84	\label{sec:method:lagrangian}
85	
86	We enforce a model-level sparsity target $\rho$ via constrained optimization.
87	Let $\bar{s} = \frac{1}{L} \sum_\ell \frac{1}{d_{\text{ff}}} \sum_j \tilde{m}_j^{(\ell)}$ denote the average fraction of retained neurons.
88	The constrained problem is:
89	\begin{align}
90	\min_\theta \; \mathcal{L}_{\text{KL}} \quad \text{s.t.} \quad \bar{s} \leq 1 - \rho.
91	\label{eq:constrained}
92	\end{align}
93	We relax this via an adaptive penalty controller:
94	\begin{align}
95	\mathcal{L} = \mathcal{L}_{\text{KL}} + \lambda \cdot \text{clamp}(|\bar{s} - (1 - \rho)| - \epsilon, \min{=}0)^2,
96	\label{eq:lagrangian}
97	\end{align}
98	where $\epsilon = 0.02$ is a deadzone margin that prevents $\lambda$ from responding to small constraint violations.
99	The penalty weight $\lambda$ is updated multiplicatively at each step:
100	\begin{align}
101	\lambda \leftarrow \begin{cases} \lambda \times 2 & \text{if } \bar{s} > (1-\rho) + \epsilon \\ \lambda \times 0.5 & \text{if } \bar{s} < (1-\rho) - \epsilon \\ \lambda & \text{otherwise} \end{cases}
102	\label{eq:dual_update}
103	\end{align}
104	with $\lambda$ clamped to $[\lambda_{\text{floor}}, \lambda_{\max}]$ where $\lambda_{\text{floor}} = 0.01$ and $\lambda_{\max} \in \{1000, 5000\}$ depending on the target.
105	The geometric doubling requires only $\lambda_{\max}$ as a user-specified hyperparameter (no step-size tuning) and reaches target sparsity within 40--110 steps for 40--50\% targets; for 30\% and 70\% targets, $\lambda$ saturates at $\lambda_{\max}$ with 1.7--5.0\% residual deviation (Appendix~\ref{app:lagrangian}, Figure~\ref{fig:lagrangian_dynamics}). The deadzone prevents oscillation once sparsity is within $\pm$2\%.\footnote{Our update rule resembles the augmented Lagrangian method but replaces gradient-based dual updates with a multiplicative schedule for training stability. We term it an adaptive penalty controller to distinguish from formal dual methods that guarantee KKT satisfaction.}
106	
107	
108	\subsection{Gradient-Based Motivation: BCE vs.\ KL}
109	\label{sec:method:gradient}
110	
111	We analyze the structural difference between BCE and KL training signals to motivate why KL distillation is better suited to global top-$k$ inference.
112	
113	\paragraph{BCE gradient structure.}
114	The standard approach trains the predictor against oracle masks $m_j^* = \mathbf{1}[|g_j| \geq \text{top-}k\text{ threshold}]$ derived from the dense model's activation magnitudes, where the threshold is the global top-$k$ cutoff across all layers (matching TEAL's inference protocol).
115	The loss decomposes per neuron:
116	\begin{align}
117	\mathcal{L}_{\text{BCE}} = -\frac{1}{d_{\text{ff}}} \sum_{j=1}^{d_{\text{ff}}} \bigl[ m_j^* \log \sigma(s_j) + (1 - m_j^*) \log(1 - \sigma(s_j)) \bigr].
118	\label{eq:bce}
119	\end{align}
120	The gradient with respect to predictor logit $s_j$ is:
121	\begin{align}
122	\frac{\partial \mathcal{L}_{\text{BCE}}}{\partial s_j} = \sigma(s_j) - m_j^*.
123	\label{eq:bce_grad}
124	\end{align}
125	This gradient depends \emph{only} on neuron $j$'s own prediction and target.
126	Each neuron is trained independently; there is no inter-neuron coupling in the learning signal.
127	
128	\paragraph{KL gradient structure.}
129	Under KL distillation, the gradient for predictor logit $s_j^{(\ell)}$ in layer $\ell$ is:
130	\begin{align}
131	\frac{\partial \mathcal{L}_{\text{KL}}}{\partial s_j^{(\ell)}} = \underbrace{\frac{\partial \mathcal{L}_{\text{KL}}}{\partial \mathbf{z}_{\text{sparse}}}}_{\text{(a)}} \cdot \underbrace{\frac{\partial \mathbf{z}_{\text{sparse}}}{\partial \mathbf{h}^{(\ell)}}}_{\text{(b)}} \cdot \underbrace{\frac{\partial \mathbf{h}^{(\ell)}}{\partial \tilde{m}_j^{(\ell)}}}_{\text{(c)}} \cdot \underbrace{\frac{\partial \tilde{m}_j^{(\ell)}}{\partial s_j^{(\ell)}}}_{\text{(d)}},
132	\label{eq:kl_grad}
133	\end{align}
134	where each factor has a distinct role:
135	\begin{itemize}
136	\item[\textbf{(a)}] The KL gradient at the output, reflecting how each logit component deviates from the dense distribution.
137	\item[\textbf{(b)}] The Jacobian through all downstream layers from layer $\ell$'s output to the final logits. This factor couples neuron $j$'s gradient to the state of every other retained neuron in layers $\ell, \ell{+}1, \ldots, L$, because the sparse hidden state propagates through subsequent attention and FFN operations.
138	\item[\textbf{(c)}] The local mask effect: $\partial \mathbf{h}^{(\ell)} / \partial \tilde{m}_j^{(\ell)} = (g_j^{(\ell)} \cdot [\mathbf{x}^{(\ell)} \mathbf{W}_u^{(\ell)}]_j) \cdot \mathbf{W}_{d,j}^{(\ell)}$, projecting through the down-projection to affect the full $d$-dimensional hidden state.
139	\item[\textbf{(d)}] The Gumbel-Sigmoid derivative: the differentiable path from logit to mask.
140	\end{itemize}
141	
142	\paragraph{The structural mismatch.}
143	The key observation is that factor (b) makes the KL gradient for neuron $j$ depend on \emph{all} other neurons' mask values.
144	BCE's factorized gradient (Eq.~\ref{eq:bce_grad}) optimizes each neuron's prediction accuracy in isolation, but TEAL inference selects neurons via a global ranking across all layers.
145	Under global top-$k$, the decision to retain neuron $j$ depends on the scores of all other neurons, a combinatorial interaction that BCE cannot capture.
146	
147	Concretely, BCE achieves high per-neuron accuracy ($>$90\% oracle agreement) yet produces poor output under TEAL, because it optimizes a proxy misaligned with output preservation under global budget allocation.
148	KL directly optimizes the end-to-end objective, with gradients that reflect inter-neuron dependencies through the computation graph.
149	
150	\paragraph{Empirical verification.}
151	Measuring gradient SNR\footnote{$\text{SNR}_\ell = \|\mathbb{E}[\nabla_{\theta_\ell} \mathcal{L}]\|_2^2 / \text{Var}[\nabla_{\theta_\ell} \mathcal{L}]$, expectation over mini-batches.} over 7 checkpoints (steps 0--300) on LLaMA-3.1-8B (C4 data) with 95\% bootstrap CI, KL achieves $5.14\times$ higher SNR than BCE at convergence ($5.877{\times}10^{-3}$ vs.\ $1.144{\times}10^{-3}$ at step 300), concentrated in early layers where factor~(b)'s Jacobian traverses the full remaining network; late layers show reduced advantage.
152	The trajectory is non-monotonic: BCE SNR exceeds KL during mid-training (steps 100--250) before KL's advantage emerges at convergence, consistent with KL's gradient coupling becoming effective only after the predictor learns a coarse mask structure (Appendix~\ref{app:snr_extended}).
153	
154	\subsection{Two-Dimensional Taxonomy of Sparsity Prediction Methods}
155	\label{sec:method:taxonomy}
156	
157	We organize prior work along two axes that capture the essential design decisions for sparsity prediction: \emph{correction granularity} (how the mask adapts to input) and \emph{training signal coupling} (whether the objective captures inter-neuron dependencies). These axes are motivated by our gradient analysis (\S\ref{sec:method:gradient}): granularity determines what information the predictor conditions on, while coupling determines whether the training signal reflects global allocation effects.
158	
159	\begin{table}[t]
160	\centering
161	\caption{Taxonomy of learned sparsity prediction methods along correction granularity (rows) and training signal coupling (columns). Our method fills the previously unexplored Per-token $\times$ Coupled cell.}
162	\label{tab:taxonomy}
163	\resizebox{\columnwidth}{!}{
164	\begin{tabular}{lccc}
165	\toprule
166	 & Decomposed (BCE) & Intermediate (MSE) & Coupled (KL) \\
167	\midrule
168	Static & --- & --- & SPON \\
169	Per-token & DejaVu, FastForward & ShadowLLM, D2DMoE & \textbf{Ours} \\
170	\bottomrule
171	\end{tabular}}
172	\end{table}
173	
174	\paragraph{Correction granularity.}
175	\emph{Static} methods~\cite{xu2026spon} learn a fixed bias vector per layer that does not depend on the input token.
176	\emph{Per-token} methods~\cite{liu2023dejavu,gautam2026fastforward,akhauri2024shadowllm,szatkowski2024d2dmoe} produce a unique mask for each input position, conditioning on the token's hidden state at each layer.
177	
178	\paragraph{Training signal coupling.}
179	\emph{Decomposed} objectives (BCE) treat each neuron independently, optimizing per-element classification against an oracle mask.
180	\emph{Intermediate} objectives (MSE on hidden states) capture local coupling within a single layer but not end-to-end output effects.
181	\emph{Coupled} objectives (KL on output distribution) propagate gradients through the full forward pass, reflecting how all mask decisions jointly affect the final distribution.
182	
183	SPON~\cite{xu2026spon} distills a per-layer bias via KL but cannot adapt to per-input neuron importance (static $\times$ coupled).
184	DejaVu~\cite{liu2023dejavu} and FastForward~\cite{gautam2026fastforward} achieve per-token granularity but use BCE, losing inter-neuron coupling: their decomposed gradient (Eq.~\ref{eq:bce_grad}) is blind to cross-neuron interactions under global allocation.
185	D2DMoE~\cite{szatkowski2024d2dmoe} provides intermediate coupling (MSE on hidden states) but not end-to-end output effects.
186	Our method combines per-token prediction with coupled KL training (Table~\ref{tab:taxonomy}), propagating gradients through all downstream layers.
187	
188	\begin{figure}[t]
189	\centering
190	\includegraphics[width=\columnwidth]{fig1_overview.pdf}
191	\caption{Method overview: a lightweight per-layer predictor produces importance scores trained via KL divergence with Gumbel-Sigmoid relaxation. At inference, scores feed TEAL's global top-$k$ allocation without compensation networks.}
192	\label{fig:overview}
193	\end{figure}
194	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9f09322b-91a8-46ed-87ce-b3f6b3144ac9",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "89cd5b7d-5d0c-4caa-a954-a2ecb3874c13",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\nWe present a KL distillation framework for training contextual sparsity predictors in SwiGLU-based language models.\nThe method replaces per-neuron binary classification (BCE) with an output-distribution objective that couples all pruning decisions through the model's forward pass and achieves competitive performance without auxiliary error compensation networks at inference.\n\n\\subsection{Problem Formulation}\n\\label{sec:method:formulation}\n\nConsider a pretrained transformer with $L$ layers, each containing a SwiGLU feed-forward network~\\cite{shazeer2020glu}.\nFor layer $\\ell$, the FFN computes:\n\\begin{align}\n\\mathbf{y}^{(\\ell)} = \\bigl(\\sigma(\\mathbf{x}^{(\\ell)} \\mathbf{W}_g^{(\\ell)}) \\odot \\mathbf{x}^{(\\ell)} \\mathbf{W}_u^{(\\ell)}\\bigr) \\mathbf{W}_d^{(\\ell)},\n\\label{eq:swiglu}\n\\end{align}\nwhere $\\mathbf{x}^{(\\ell)} \\in \\mathbb{R}^{d}$ is the hidden state after attention ($d{=}4096$), $\\sigma$ denotes SiLU, $\\mathbf{W}_g^{(\\ell)}, \\mathbf{W}_u^{(\\ell)} \\in \\mathbb{R}^{d \\times d_{\\text{ff}}}$ and $\\mathbf{W}_d^{(\\ell)} \\in \\mathbb{R}^{d_{\\text{ff}} \\times d}$ are the gate, up-projection, and down-projection matrices, and $d_{\\text{ff}}{=}14{,}336$.\n\nDefine the gate activation $\\mathbf{g}^{(\\ell)} = \\sigma(\\mathbf{x}^{(\\ell)} \\mathbf{W}_g^{(\\ell)}) \\in \\mathbb{R}^{d_{\\text{ff}}}$.\nEach element $g_j^{(\\ell)}$ determines the contribution of neuron $j$ to the output.\nWe introduce a binary mask $\\mathbf{m}^{(\\ell)} \\in \\{0,1\\}^{d_{\\text{ff}}}$ that zeros out pruned neurons:\n\\begin{align}\n\\mathbf{y}_{\\text{sparse}}^{(\\ell)} = \\bigl(\\mathbf{m}^{(\\ell)} \\odot \\mathbf{g}^{(\\ell)} \\odot \\mathbf{x}^{(\\ell)} \\mathbf{W}_u^{(\\ell)}\\bigr) \\mathbf{W}_d^{(\\ell)}.\n\\label{eq:sparse_ffn}\n\\end{align}\nOur goal is to learn a mask predictor $f_\\theta^{(\\ell)}(\\mathbf{h}) \\to \\mathbf{s}^{(\\ell)} \\in (0,1)^{d_{\\text{ff}}}$ that produces per-neuron importance scores from the pre-FFN hidden state $\\mathbf{h}$.\nAt inference, the scores are fed to a global top-$k$ allocation mechanism~\\cite{liu2025teal} that distributes the sparsity budget across layers non-uniformly, retaining the $(1{-}\\rho) \\times L \\times d_{\\text{ff}}$ highest-scoring neurons model-wide for a target sparsity ratio $\\rho$.\n\n\n\\subsection{Predictor Architecture}\n\\label{sec:method:predictor}\n\nEach layer $\\ell$ has an independent two-layer MLP predictor:\n\\begin{align}\nf_\\theta^{(\\ell)}(\\mathbf{h}) = \\text{GELU}(\\mathbf{h} \\mathbf{W}_1^{(\\ell)}) \\, \\mathbf{W}_2^{(\\ell)},\n\\label{eq:predictor}\n\\end{align}\nwhere $\\mathbf{W}_1^{(\\ell)} \\in \\mathbb{R}^{d \\times d_b}$ and $\\mathbf{W}_2^{(\\ell)} \\in \\mathbb{R}^{d_b \\times d_{\\text{ff}}}$ with bottleneck dimension $d_b{=}128$.\nThe predictor takes the hidden state after attention (before the FFN) and outputs $d_{\\text{ff}}$-dimensional logits $\\mathbf{s}^{(\\ell)}$, from which the mask is derived.\n\nEach predictor has $(4096 \\times 128) + (128 \\times 14336) = 2.37\\text{M}$ parameters.\nWith 32 independent predictors (one per layer), the total overhead is 75.9M parameters, less than 1\\% of the 8B base model.\nThe predictors operate independently across layers, requiring no cross-layer communication at inference.\n\n\n\\subsection{Gumbel-Sigmoid Relaxation}\n\\label{sec:method:gumbel}\n\nThe hard mask $m_j = \\mathbf{1}[s_j > \\text{threshold}]$ is non-differentiable, preventing gradient flow from the KL objective through the mask to the predictor parameters.\nWe apply Gumbel-Sigmoid relaxation~\\cite{jang2017gumbel} to produce differentiable soft masks:\n\\begin{align}\n\\tilde{m}_j = \\sigma_\\tau\\!\\left(\\log \\frac{s_j}{1 - s_j} + g_1 - g_2\\right), \\quad g_1, g_2 \\sim \\text{Gumbel}(0,1),\n\\label{eq:gumbel}\n\\end{align}\nwhere $\\sigma_\\tau(x) = \\text{sigmoid}(x / \\tau)$ and $\\tau$ is a temperature parameter.\nThe Gumbel noise provides stochastic exploration of mask configurations during training, while the temperature controls sharpness: as $\\tau \\to 0$, $\\tilde{m}_j$ approaches a binary decision.\n\nWe anneal $\\tau$ linearly from 1.0 to 0.1 over training.\nAt high temperature, the soft mask permits gradient flow through all neurons for broad exploration.\nAs temperature decreases, the mask concentrates on confident decisions, approximating the hard allocation used at inference.\n\n\\paragraph{Comparison with Straight-Through Estimation.}\nThe straight-through estimator (STE)~\\cite{bengio2013ste} applies a hard threshold in the forward pass and passes gradients through unchanged ($\\partial m / \\partial s = 1$).\nIn our setting, STE produces discontinuous gradient signals: small parameter changes can flip many neurons simultaneously, causing violent oscillations in the penalty weight and failure to converge to the target sparsity.\nGumbel relaxation eliminates this pathology, contributing a 34.5\\% improvement (PPL 15.77 $\\to$ 11.79 at 50\\% sparsity), as we verify empirically in \\S\\ref{sec:experiments}.\n\n\n\\subsection{KL Divergence Training Objective}\n\\label{sec:method:kl}\n\nLet $\\mathbf{z}_{\\text{dense}}$ denote the output logits from a full dense forward pass, and $\\mathbf{z}_{\\text{sparse}}$ the logits from a forward pass with predictor-generated soft masks $\\{\\tilde{\\mathbf{m}}^{(\\ell)}\\}_\\ell$ applied at every layer.\nWe minimize the forward KL divergence between the dense and sparse output distributions:\n\\begin{align}\n\\mathcal{L}_{\\text{KL}} = D_{\\text{KL}}(p_{\\text{dense}} \\,\\|\\, p_{\\text{sparse}}) = \\sum_{v} p_{\\text{dense}}^{(v)} \\log \\frac{p_{\\text{dense}}^{(v)}}{p_{\\text{sparse}}^{(v)}},\n\\label{eq:kl_loss}\n\\end{align}\nwhere $p_{\\text{dense}} = \\text{softmax}(\\mathbf{z}_{\\text{dense}})$ and $p_{\\text{sparse}} = \\text{softmax}(\\mathbf{z}_{\\text{sparse}})$, summed over the vocabulary $v$ and averaged over sequence positions.\nThe base model is frozen; only the predictor parameters receive gradients.\n\nWe use forward KL (mean-seeking) rather than reverse KL, as the goal is to preserve the dense model's primary predictions rather than explore alternative modes; \\S\\ref{sec:experiments} validates this choice with ablations over divergence direction (forward KL outperforms JSD by 6.4\\% and reverse KL by 8.6\\%).\nNo temperature scaling ($T{=}1$) is applied~\\cite{hinton2015distilling}.\n\n\n\\subsection{Adaptive Penalty Sparsity Controller}\n\\label{sec:method:lagrangian}\n\nWe enforce a model-level sparsity target $\\rho$ via constrained optimization.\nLet $\\bar{s} = \\frac{1}{L} \\sum_\\ell \\frac{1}{d_{\\text{ff}}} \\sum_j \\tilde{m}_j^{(\\ell)}$ denote the average fraction of retained neurons.\nThe constrained problem is:\n\\begin{align}\n\\min_\\theta \\; \\mathcal{L}_{\\text{KL}} \\quad \\text{s.t.} \\quad \\bar{s} \\leq 1 - \\rho.\n\\label{eq:constrained}\n\\end{align}\nWe relax this via an adaptive penalty controller:\n\\begin{align}\n\\mathcal{L} = \\mathcal{L}_{\\text{KL}} + \\lambda \\cdot \\text{clamp}(|\\bar{s} - (1 - \\rho)| - \\epsilon, \\min{=}0)^2,\n\\label{eq:lagrangian}\n\\end{align}\nwhere $\\epsilon = 0.02$ is a deadzone margin that prevents $\\lambda$ from responding to small constraint violations.\nThe penalty weight $\\lambda$ is updated multiplicatively at each step:\n\\begin{align}\n\\lambda \\leftarrow \\begin{cases} \\lambda \\times 2 & \\text{if } \\bar{s} > (1-\\rho) + \\epsilon \\\\ \\lambda \\times 0.5 & \\text{if } \\bar{s} < (1-\\rho) - \\epsilon \\\\ \\lambda & \\text{otherwise} \\end{cases}\n\\label{eq:dual_update}\n\\end{align}\nwith $\\lambda$ clamped to $[\\lambda_{\\text{floor}}, \\lambda_{\\max}]$ where $\\lambda_{\\text{floor}} = 0.01$ and $\\lambda_{\\max} \\in \\{1000, 5000\\}$ depending on the target.\nThe geometric doubling requires only $\\lambda_{\\max}$ as a user-specified hyperparameter (no step-size tuning) and reaches target sparsity within 40--110 steps for 40--50\\% targets; for 30\\% and 70\\% targets, $\\lambda$ saturates at $\\lambda_{\\max}$ with 1.7--5.0\\% residual deviation (Appendix~\\ref{app:lagrangian}, Figure~\\ref{fig:lagrangian_dynamics}). The deadzone prevents oscillation once sparsity is within $\\pm$2\\%.\\footnote{Our update rule resembles the augmented Lagrangian method but replaces gradient-based dual updates with a multiplicative schedule for training stability. We term it an adaptive penalty controller to distinguish from formal dual methods that guarantee KKT satisfaction.}\n\n\n\\subsection{Gradient-Based Motivation: BCE vs.\\ KL}\n\\label{sec:method:gradient}\n\nWe analyze the structural difference between BCE and KL training signals to motivate why KL distillation is better suited to global top-$k$ inference.\n\n\\paragraph{BCE gradient structure.}\nThe standard approach trains the predictor against oracle masks $m_j^* = \\mathbf{1}[|g_j| \\geq \\text{top-}k\\text{ threshold}]$ derived from the dense model's activation magnitudes, where the threshold is the global top-$k$ cutoff across all layers (matching TEAL's inference protocol).\nThe loss decomposes per neuron:\n\\begin{align}\n\\mathcal{L}_{\\text{BCE}} = -\\frac{1}{d_{\\text{ff}}} \\sum_{j=1}^{d_{\\text{ff}}} \\bigl[ m_j^* \\log \\sigma(s_j) + (1 - m_j^*) \\log(1 - \\sigma(s_j)) \\bigr].\n\\label{eq:bce}\n\\end{align}\nThe gradient with respect to predictor logit $s_j$ is:\n\\begin{align}\n\\frac{\\partial \\mathcal{L}_{\\text{BCE}}}{\\partial s_j} = \\sigma(s_j) - m_j^*.\n\\label{eq:bce_grad}\n\\end{align}\nThis gradient depends \\emph{only} on neuron $j$'s own prediction and target.\nEach neuron is trained independently; there is no inter-neuron coupling in the learning signal.\n\n\\paragraph{KL gradient structure.}\nUnder KL distillation, the gradient for predictor logit $s_j^{(\\ell)}$ in layer $\\ell$ is:\n\\begin{align}\n\\frac{\\partial \\mathcal{L}_{\\text{KL}}}{\\partial s_j^{(\\ell)}} = \\underbrace{\\frac{\\partial \\mathcal{L}_{\\text{KL}}}{\\partial \\mathbf{z}_{\\text{sparse}}}}_{\\text{(a)}} \\cdot \\underbrace{\\frac{\\partial \\mathbf{z}_{\\text{sparse}}}{\\partial \\mathbf{h}^{(\\ell)}}}_{\\text{(b)}} \\cdot \\underbrace{\\frac{\\partial \\mathbf{h}^{(\\ell)}}{\\partial \\tilde{m}_j^{(\\ell)}}}_{\\text{(c)}} \\cdot \\underbrace{\\frac{\\partial \\tilde{m}_j^{(\\ell)}}{\\partial s_j^{(\\ell)}}}_{\\text{(d)}},\n\\label{eq:kl_grad}\n\\end{align}\nwhere each factor has a distinct role:\n\\begin{itemize}\n\\item[\\textbf{(a)}] The KL gradient at the output, reflecting how each logit component deviates from the dense distribution.\n\\item[\\textbf{(b)}] The Jacobian through all downstream layers from layer $\\ell$'s output to the final logits. This factor couples neuron $j$'s gradient to the state of every other retained neuron in layers $\\ell, \\ell{+}1, \\ldots, L$, because the sparse hidden state propagates through subsequent attention and FFN operations.\n\\item[\\textbf{(c)}] The local mask effect: $\\partial \\mathbf{h}^{(\\ell)} / \\partial \\tilde{m}_j^{(\\ell)} = (g_j^{(\\ell)} \\cdot [\\mathbf{x}^{(\\ell)} \\mathbf{W}_u^{(\\ell)}]_j) \\cdot \\mathbf{W}_{d,j}^{(\\ell)}$, projecting through the down-projection to affect the full $d$-dimensional hidden state.\n\\item[\\textbf{(d)}] The Gumbel-Sigmoid derivative: the differentiable path from logit to mask.\n\\end{itemize}\n\n\\paragraph{The structural mismatch.}\nThe key observation is that factor (b) makes the KL gradient for neuron $j$ depend on \\emph{all} other neurons' mask values.\nBCE's factorized gradient (Eq.~\\ref{eq:bce_grad}) optimizes each neuron's prediction accuracy in isolation, but TEAL inference selects neurons via a global ranking across all layers.\nUnder global top-$k$, the decision to retain neuron $j$ depends on the scores of all other neurons, a combinatorial interaction that BCE cannot capture.\n\nConcretely, BCE achieves high per-neuron accuracy ($>$90\\% oracle agreement) yet produces poor output under TEAL, because it optimizes a proxy misaligned with output preservation under global budget allocation.\nKL directly optimizes the end-to-end objective, with gradients that reflect inter-neuron dependencies through the computation graph.\n\n\\paragraph{Empirical verification.}\nMeasuring gradient SNR\\footnote{$\\text{SNR}_\\ell = \\|\\mathbb{E}[\\nabla_{\\theta_\\ell} \\mathcal{L}]\\|_2^2 / \\text{Var}[\\nabla_{\\theta_\\ell} \\mathcal{L}]$, expectation over mini-batches.} over 7 checkpoints (steps 0--300) on LLaMA-3.1-8B (C4 data) with 95\\% bootstrap CI, KL achieves $5.14\\times$ higher SNR than BCE at convergence ($5.877{\\times}10^{-3}$ vs.\\ $1.144{\\times}10^{-3}$ at step 300), concentrated in early layers where factor~(b)'s Jacobian traverses the full remaining network; late layers show reduced advantage.\nThe trajectory is non-monotonic: BCE SNR exceeds KL during mid-training (steps 100--250) before KL's advantage emerges at convergence, consistent with KL's gradient coupling becoming effective only after the predictor learns a coarse mask structure (Appendix~\\ref{app:snr_extended}).\n\n\\subsection{Two-Dimensional Taxonomy of Sparsity Prediction Methods}\n\\label{sec:method:taxonomy}\n\nWe organize prior work along two axes that capture the essential design decisions for sparsity prediction: \\emph{correction granularity} (how the mask adapts to input) and \\emph{training signal coupling} (whether the objective captures inter-neuron dependencies). These axes are motivated by our gradient analysis (\\S\\ref{sec:method:gradient}): granularity determines what information the predictor conditions on, while coupling determines whether the training signal reflects global allocation effects.\n\n\\begin{table}[t]\n\\centering\n\\caption{Taxonomy of learned sparsity prediction methods along correction granularity (rows) and training signal coupling (columns). Our method fills the previously unexplored Per-token $\\times$ Coupled cell.}\n\\label{tab:taxonomy}\n\\resizebox{\\columnwidth}{!}{\n\\begin{tabular}{lccc}\n\\toprule\n & Decomposed (BCE) & Intermediate (MSE) & Coupled (KL) \\\\\n\\midrule\nStatic & --- & --- & SPON \\\\\nPer-token & DejaVu, FastForward & ShadowLLM, D2DMoE & \\textbf{Ours} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Correction granularity.}\n\\emph{Static} methods~\\cite{xu2026spon} learn a fixed bias vector per layer that does not depend on the input token.\n\\emph{Per-token} methods~\\cite{liu2023dejavu,gautam2026fastforward,akhauri2024shadowllm,szatkowski2024d2dmoe} produce a unique mask for each input position, conditioning on the token's hidden state at each layer.\n\n\\paragraph{Training signal coupling.}\n\\emph{Decomposed} objectives (BCE) treat each neuron independently, optimizing per-element classification against an oracle mask.\n\\emph{Intermediate} objectives (MSE on hidden states) capture local coupling within a single layer but not end-to-end output effects.\n\\emph{Coupled} objectives (KL on output distribution) propagate gradients through the full forward pass, reflecting how all mask decisions jointly affect the final distribution.\n\nSPON~\\cite{xu2026spon} distills a per-layer bias via KL but cannot adapt to per-input neuron importance (static $\\times$ coupled).\nDejaVu~\\cite{liu2023dejavu} and FastForward~\\cite{gautam2026fastforward} achieve per-token granularity but use BCE, losing inter-neuron coupling: their decomposed gradient (Eq.~\\ref{eq:bce_grad}) is blind to cross-neuron interactions under global allocation.\nD2DMoE~\\cite{szatkowski2024d2dmoe} provides intermediate coupling (MSE on hidden states) but not end-to-end output effects.\nOur method combines per-token prediction with coupled KL training (Table~\\ref{tab:taxonomy}), propagating gradients through all downstream layers.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_overview.pdf}\n\\caption{Method overview: a lightweight per-layer predictor produces importance scores trained via KL divergence with Gumbel-Sigmoid relaxation. At inference, scores feed TEAL's global top-$k$ allocation without compensation networks.}\n\\label{fig:overview}\n\\end{figure}\n",
      "numLines": 194,
      "startLine": 1,
      "totalLines": 194
    }
  },
  "sourceToolAssistantUUID": "9f09322b-91a8-46ed-87ce-b3f6b3144ac9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-18T12:24:59.771Z_

<details open><summary>🔧 Tool call — Read · `toolu_01H6EanuGSbuTcF4wHsY8bx8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "89cd5b7d-5d0c-4caa-a954-a2ecb3874c13",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "e067bc63-72dd-431c-9e9b-1c47dc14d751",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 35 · 2026-05-18T12:24:59.776Z_

<details><summary>↩ Tool result · `toolu_01H6EanuGSbuTcF4wHsY8bx8`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	
6	\paragraph{Model and Predictor.}
7	We evaluate on LLaMA-3.1-8B~\cite{grattafiori2024llama3}, which uses SwiGLU FFN blocks~\cite{shazeer2020glu} with $d_{\text{model}}=4096$ and $d_{\text{ff}}=14336$ across 32 layers.
8	The sparsity predictor is a two-layer MLP with 2.37M parameters per layer (75.9M total), implemented as Linear($4096 \to 128$) + GELU + Linear($128 \to 14336$), trained to produce per-neuron importance scores that minimize output-distribution divergence under sparsity.
9	
10	\paragraph{Training.}
11	All predictors are trained for 1000 steps on WikiText-103 with sequence length 2048 and batch size 4, using AdamW~\cite{loshchilov2019adamw} with learning rate $1 \times 10^{-3}$, weight decay $5 \times 10^{-2}$, and cosine decay.
12	The KL predictor uses Gumbel-Sigmoid relaxation~\cite{jang2017gumbel} with temperature $\tau=1.0$ annealed to $0.1$ over training.
13	
14	\paragraph{Evaluation.}
15	We report perplexity on WikiText-2~\cite{merity2017pointer} (seq\_len=2048) and downstream accuracy on ARC-Challenge (25-shot), WinoGrande (5-shot), MMLU (5-shot), and GSM8K (8-shot).
16	
17	\paragraph{Inference Protocol.}
18	At inference, the predictor produces per-neuron scores that are passed to TEAL's global top-$k$ allocation mechanism~\cite{liu2025teal}, which distributes the sparsity budget across layers non-uniformly.
19	We term this \textit{predictor-TEAL}: the predictor replaces TEAL's magnitude-based scoring while retaining its allocation strategy.
20	
21	\paragraph{Baselines.}
22	We compare against: (1) \textbf{Vanilla TEAL}~\cite{liu2025teal}, which uses activation magnitudes directly; (2) \textbf{BCE predictor} (DejaVu-style~\cite{liu2023dejavu}), trained with per-neuron binary cross-entropy on magnitude-based oracle masks for 1000 and 2700 steps; (3) \textbf{Uniform allocation}, which distributes the sparsity budget equally across layers; and (4) \textbf{WINA}~\cite{liu2025teal}, an importance-weighted variant.
23	
24	
25	\subsection{Main Results}
26	
27	Table~\ref{tab:main} presents the primary comparison. We recommend uniform allocation for deployment (best downstream preservation); global allocation is analyzed to understand allocation-quality tradeoffs (\S\ref{sec:scaling}).
28	At 30\% sparsity, KL distillation with global TEAL allocation achieves PPL 8.96$\pm$0.02 (3-seed) and reduces TEAL's degradation from dense (10.97 $\to$ 8.96, an 18\% improvement). % exp_id: kl30_3seed_global
29	The advantage holds across additional downstream benchmarks (Appendix~\ref{app:downstream}).
30	Uniform allocation at 30\% provides stable downstream performance (MMLU 40.7$\pm$1.3\%, 3-seed) while global top-$k$ exhibits high seed variance (35.7$\pm$9.5\%), with late-layer starvation (L31 retention 28.4\%) interacting with predictor initialization (\S\ref{sec:scaling}). % exp_id: bench_kl30_uniform, kl30_3seed
31	
32	At 50\% sparsity, KL distillation over vanilla TEAL widens the PPL advantage: 11.79 vs.\ 23.31, a 49\% reduction. % exp_id: bench_kl50_global, bench_teal50
33	The predictor generalizes to C4 validation at both 30\% (PPL 16.03$\pm$0.01, 2-seed) and 50\% (52.5\% over TEAL; Appendix~\ref{app:ood}).
34	However, all methods exhibit downstream collapse on MMLU (28.1$\pm$0.2\% vs.\ 28.0$\pm$0.6\%, both $\approx$ random, 3-seed) and GSM8K ($<$2.2\%); this is a capacity-limited regime where no allocation strategy can recover. % exp_id: bench_kl50_global, d030_kl50_uniform, multi_seed_kl50_global
35	
36	\begin{table}[t]
37	\centering
38	\caption{Main results on LLaMA-3.1-8B. PPL$\downarrow$ on WikiText-2; accuracy$\uparrow$ on downstream tasks. \textbf{Bold}: best among compensation-free methods per sparsity level. BCE follows the DejaVu~\cite{liu2023dejavu} predictor pipeline (per-neuron BCE on magnitude oracles) with a FastForward-style~\cite{gautam2026fastforward} compensation network (67.2M params) applied post-masking; no TEAL allocation. Entries with $\pm$ report 3-seed mean$\pm$std ($s \in \{42, 123, 456\}$); 50\% uniform PPL is 3-seed ($11.92 \pm 0.07$; Appendix~\ref{app:stability}); remaining entries use seed 42.}
39	\label{tab:main}
40	\resizebox{\columnwidth}{!}{
41	\begin{tabular}{llccccc}
42	\toprule
43	Sparsity & Method & PPL$\downarrow$ & ARC-c & WG & MMLU & GSM8K \\
44	\midrule
45	0\% & Dense & 6.12 & 58.28 & 78.06 & 65.27 & 48.75 \\
46	\midrule
47	\multirow{3}{*}{30\%}
48	& TEAL vanilla & 10.97 & 42.32 & 66.06 & 38.61 & 7.88 \\ % exp_id: bench_teal30
49	& KL global (Ours) & 8.96$\pm$0.02 & \textbf{43.8$\pm$3.6} & \textbf{70.2$\pm$0.9} & 35.7$\pm$9.5 & \textbf{8.0$\pm$0.7} \\ % exp_id: kl30_3seed_global
50	& KL uniform & \textbf{8.82} & 40.78 & 68.59 & \textbf{40.7$\pm$1.3} & 7.35 \\ % exp_id: kl30_3seed_uniform
51	\midrule
52	\multirow{4}{*}{50\%}
53	& TEAL vanilla & 23.31 & 28.41 & 53.04 & \textbf{28.32} & 1.97 \\ % exp_id: bench_teal50
54	& KL global (Ours) & \textbf{11.79} & \textbf{32.85} & \textbf{63.46} & 28.1$\pm$0.2 & 1.29 \\ % exp_id: multi_seed_kl50_global
55	& KL uniform & 11.96 & 32.76 & 62.90 & 28.0$\pm$0.6 & \textbf{2.12} \\ % exp_id: multi_seed_kl50_uniform
56	& BCE (2700 steps)$^\ast$ & 28.13$\pm$0.20 & 27.6$\pm$0.6 & 51.8$\pm$0.6 & 26.1$\pm$0.5 & 2.1$\pm$0.2 \\ % exp_id: bce50_3seed
57	\bottomrule
58	\end{tabular}}
59	\end{table}
60	
61	
62	\subsection{Extended Training Analysis}
63	\label{sec:isocompute}
64	
65	To test whether BCE simply requires more compute, we train it for 2700 steps (2.71$\times$ the KL step budget, approximately equal wall-clock time: $\sim$46 min BCE vs.\ $\sim$45 min KL on RTX PRO 6000).
66	The BCE predictor achieves PPL 28.13$\pm$0.20 (3-seed), still 2.39$\times$ worse than KL at 1000 steps (PPL 11.79). % exp_id: bce50_3seed
67	The difference is systematic, not due to architectural or compute limitations: both predictors use identical architectures and TEAL allocation, yet BCE achieves +7pp oracle F1 (0.613 vs.\ 0.540) with 139\% worse PPL (28.13 vs.\ 11.79). KL's near-random precision (0.51) is consistent with learning a mask optimized for distributional fidelity rather than magnitude matching. % exp_id: f1_oracle_analysis, bce_isocompute_s42
68	Coupled training correlates with better output preservation, but disentangling gradient coupling from oracle quality remains open (BCE uses magnitude oracles while KL optimizes output directly; an ablation using KL-derived masks as BCE targets would isolate the effect).
69	
70	
71	\subsection{Ablation Studies}
72	
73	Table~\ref{tab:ablation} isolates the contribution of each design choice at 50\% sparsity.
74	
75	\begin{table}[t]
76	\centering
77	\caption{Ablation at 50\% sparsity on LLaMA-3.1-8B (WikiText-2 PPL$\downarrow$, unified benchmark protocol).}
78	\label{tab:ablation}
79	\small
80	\begin{tabular}{lcc}
81	\toprule
82	Configuration & PPL$\downarrow$ & $\Delta$ from Ours \\
83	\midrule
84	\multicolumn{3}{l}{\textit{KL-based variants}} \\
85	Forward KL + Gumbel (Ours) & \textbf{11.79} & --- \\ % exp_id: bench_kl50_global
86	JSD (symmetric) + Gumbel & 12.54 & +0.75 \\ % exp_id: jsd_ablation_s42
87	Reverse KL + Gumbel & 12.80 & +1.01 \\ % exp_id: reverse_kl_ablation_s42
88	Forward KL + STE & 15.77 & +3.98 \\ % exp_id: ste_baseline_s42
89	\midrule
90	\multicolumn{3}{l}{\textit{BCE-based variants}} \\
91	BCE + Compensation (hard mask) & 25.44 & +13.65 \\ % exp_id: bce_comp_staged_s42
92	BCE (no compensation) & 27.97 & +16.18 \\ % exp_id: eval_bce_v3_s42
93	BCE + Gumbel + Penalty (no KL) & 38.02 & +26.23 \\ % exp_id: bce_gumbel_lagrangian_isolation
94	\bottomrule
95	\end{tabular}
96	\end{table}
97	
98	\paragraph{Gumbel vs.\ STE.}
99	Replacing Gumbel-Sigmoid with STE~\cite{bengio2013ste} degrades PPL from 11.79 to 15.77 (+3.98), accounting for 34.5\% of the improvement over vanilla TEAL. % exp_id: ste_baseline_s42
100	
101	\paragraph{Divergence Direction.}
102	Forward KL (mode-covering) outperforms JSD (+6.4\%) and reverse KL (+8.6\%), consistent with the SNR analysis in \S\ref{sec:method:gradient}: complete teacher supervision is associated with better global allocation quality. % exp_id: jsd_ablation_s42, reverse_kl_ablation_s42
103	This contrasts with MiniLLM~\cite{gu2024minillm} (reverse KL for generation); in mask prediction, mode-covering ensures no important neuron is omitted.
104	
105	\paragraph{SPON Contribution.}
106	Adding SPON~\cite{xu2026spon} bias correction reduces PPL from 12.08 to 11.79 (2.4\% relative); see \S\ref{sec:spon} for decomposition.\footnote{SPON analysis uses \texttt{evaluate.py}; main results use the unified benchmark.} % exp_id: spon_2048_s42, mvp_kl_norm_v2_s42
107	
108	\paragraph{Loss Function Isolation.}
109	BCE with identical Gumbel-Sigmoid and penalty yields PPL 38.02, worse than vanilla BCE (27.97): the penalty interferes with per-neuron optimization without global coordination. % exp_id: bce_gumbel_lagrangian_isolation
110	The loss effect ($\Delta$PPL=26.23) is $6.6\times$ the relaxation effect ($\Delta$PPL=3.98).
111	
112	\paragraph{Compensation Redundancy.}
113	Adding compensation~\cite{gautam2026fastforward} (+67.2M params) to KL provides no benefit at either tested sparsity: at 50\%, all five metrics are identical to KL-only; at 30\%, PPL 8.97$\pm$0.01 vs.\ 8.96$\pm$0.03 (2-seed). BCE requires compensation (27.97$\to$25.44), yet remains $2.16\times$ worse than KL without it. Training converges by step 700 (Appendix~\ref{app:comp_convergence}). % exp_id: kl_comp_30_s42, kl_comp_30_s456, kl_comp_50_s42, bce_comp_staged_s42
114	
115	\paragraph{Hyperparameter Robustness.}
116	Appendix~\ref{app:db_sensitivity} confirms robustness to predictor capacity ($d_b$, $<$3\%), temperature ($<$1.8\%), and training steps (saturated by 800). % exp_id: db_sensitivity_sweep, tau_schedule_sweep, training_steps_sweep
117	
118	
119	\subsection{Sparsity Scaling and Regime Analysis}
120	\label{sec:scaling}
121	
122	Table~\ref{tab:scaling} and Figure~\ref{fig:sparsity_sweep} show PPL as a function of sparsity for the KL predictor under global allocation and vanilla TEAL.
123	
124	\begin{figure}[t]
125	\centering
126	\includegraphics[width=\columnwidth]{fig2_sparsity_sweep.pdf}
127	\caption{Perplexity scaling with sparsity. The KL predictor's advantage grows disproportionately as more neurons are pruned.}
128	\label{fig:sparsity_sweep}
129	\end{figure}
130	
131	\begin{table}[t]
132	\centering
133	\caption{PPL scaling with sparsity (WikiText-2). KL advantage grows disproportionately with sparsity.}
134	\label{tab:scaling}
135	\small
136	\begin{tabular}{lccc}
137	\toprule
138	Sparsity & KL (Ours) & TEAL vanilla & Relative advantage \\
139	\midrule
140	30\% & \textbf{8.96} & 10.97 & 18\% \\ % exp_id: kl30_3seed_global
141	50\% & \textbf{11.79} & 23.31 & 49\% \\ % exp_id: bench_kl50_global
142	70\% & \textbf{17.91} & 100.11 & 82\% \\ % exp_id: kl_70_global_teal
143	\bottomrule
144	\end{tabular}
145	\end{table}
146	
147	The KL advantage grows from 18\% at 30\% to 82\% at 70\%, where TEAL collapses (PPL 100.11) while the learned predictor maintains coherent allocation.
148	In absolute terms, KL/Dense degradation is $1.47\times$ at 30\%, $1.93\times$ at 50\%, and $2.93\times$ at 70\%, compared to TEAL/Dense ratios of $1.79\times$, $3.81\times$, and $16.4\times$ respectively.
149	
150	\paragraph{Three Operating Regions.}
151	Table~\ref{tab:phase} presents global vs.\ uniform allocation at three sparsity levels and reveals qualitative shifts in allocation preference. Denser sampling (e.g., 35\% sparsity) would be needed to precisely locate region boundaries.
152	
153	\begin{table}[t]
154	\centering
155	\caption{Allocation analysis: global (TEAL) vs.\ uniform per-layer allocation across sparsity levels. Entries with $\pm$ report 3-seed mean$\pm$std; remaining entries use seed 42. Each row uses a predictor trained at the respective sparsity target.}
156	\label{tab:phase}
157	\resizebox{\columnwidth}{!}{
158	\begin{tabular}{llccccc}
159	\toprule
160	Sparsity & Allocation & PPL$\downarrow$ & ARC-c & WG & MMLU & GSM8K \\
161	\midrule
162	0\% & Dense & 6.12 & 58.28 & 78.06 & 65.27 & 48.75 \\
163	\midrule
164	\multirow{3}{*}{30\%}
165	& TEAL vanilla & 10.97 & 42.32 & 66.06 & 38.61 & 7.88 \\ % exp_id: bench_teal30
166	& KL global & 8.96$\pm$0.02 & \textbf{43.8$\pm$3.6} & \textbf{70.2$\pm$0.9} & 35.7$\pm$9.5 & \textbf{8.0$\pm$0.7} \\ % exp_id: kl30_3seed_global
167	& KL uniform & \textbf{8.82} & 40.78 & 68.59 & \textbf{40.7$\pm$1.3} & 7.35 \\ % exp_id: kl30_3seed_uniform
168	\midrule
169	\multirow{2}{*}{40\%}
170	& KL global & 10.12 & 40.96 & 65.35 & \textbf{38.06} & \textbf{5.00} \\ % exp_id: bench_kl40_global
171	& KL uniform & \textbf{8.36} & \textbf{41.81} & \textbf{67.17} & 30.68 & 3.94 \\ % exp_id: d030_kl40_uniform
172	\midrule
173	\multirow{3}{*}{50\%}
174	& TEAL vanilla & 23.31 & 28.41 & 53.04 & \textbf{28.32} & 1.97 \\ % exp_id: bench_teal50
175	& KL global & \textbf{11.79} & \textbf{32.85} & \textbf{63.46} & 28.1$\pm$0.2 & 1.29 \\ % exp_id: multi_seed_kl50_global
176	& KL uniform & 11.96 & 32.76 & 62.90 & 28.0$\pm$0.6 & \textbf{2.12} \\ % exp_id: multi_seed_kl50_uniform
177	\bottomrule
178	\end{tabular}}
179	\end{table}
180	
181	The allocation preference is \emph{non-monotonic}. We observe three qualitative behaviors at the sampled sparsity levels (7--8B scale):
182	
183	\noindent\textbf{Budget-surplus ($\leq$30\%).}
184	Uniform allocation provides $7.5\times$ smaller cross-seed MMLU standard deviation ($\sigma$: 1.3pp vs.\ 9.5pp), eliminating catastrophic seed-dependent degradation under global top-$k$ (MMLU 35.7$\pm$9.5\% vs.\ 40.7$\pm$1.3\%, 3-seed). Vanilla TEAL is deterministic (magnitude-based) and exhibits zero cross-seed variance; the observed instability arises from the interaction between learned predictor initialization and global top-$k$'s layer-budget distribution, not from the distillation objective itself (PPL cross-seed CV $<$ 0.3\%).
185	Global top-$k$ starves late layers (L31: 28.4\%, std/mean$=$1.89), and this starvation interacts unpredictably with predictor initialization (Appendix~\ref{app:lagrangian}). % exp_id: kl30_3seed
186	
187	\noindent\textbf{Budget-constrained ($\sim$40\%).}
188	The preference reverses: global achieves MMLU 38.06\% vs.\ uniform's 30.68\% (+7.4pp). % exp_id: bench_kl40_global, d030_kl40_uniform
189	PPL remains low (8.36) but downstream accuracy degrades; PPL is a poor proxy for reasoning.
190	
191	\noindent\textbf{Capacity-limited ($\geq$50\%).}
192	Global/uniform gap vanishes (MMLU 28.1$\pm$0.2\% vs.\ 28.0$\pm$0.6\%, $\sigma\leq$0.6pp; contrast 9.5pp at 30\%), consistent with capacity limitation. % exp_id: multi_seed_kl50_global, multi_seed_kl50_uniform
193	Late-layer starvation persists across levels (L24--31 retention: 50.1/34.2/22.6\% at 30/50/70\% sparsity; Figure~\ref{fig:retention}), consistent on both 7--8B models (\S\ref{sec:cross_arch}).
194	Under uniform allocation, 53\% of the Dense$\to$KL gap is predictor approximation vs.\ 47\% budget allocation (Appendix~\ref{app:db_sensitivity}).
195	
196	
197	\subsection{SPON Orthogonality Analysis}
198	\label{sec:spon}
199	
200	At 50\% sparsity, the predictor's hidden-state perturbation (L2=482.65) and SPON's additive correction (L2=76.2, cosine similarity 0.196) are weakly correlated ($R^2$=0.038); SPON yields only 2.4\% PPL improvement (12.08$\to$11.79); the KL predictor already captures most recoverable signal. % exp_id: spon_decomposition, spon_2048_s42, mvp_kl_norm_v2_s42
201	
202	\paragraph{Cross-Architecture Validation.}
203	\label{sec:cross_arch}
204	Table~\ref{tab:cross_arch} evaluates on Mistral-7B-v0.3~\cite{jiang2023mistral} (GQA + sliding window, dense PPL 5.52).
205	
206	\begin{table}[t]
207	\centering
208	\caption{Cross-architecture comparison (WikiText-2 PPL$\downarrow$). Adv = TEAL\,/\,KL ratio. LLaMA uses global top-$k$; Mistral uses uniform allocation (matched within each architecture).}
209	\label{tab:cross_arch}
210	\small
211	\begin{tabular}{l@{\hspace{4pt}}cc@{\hspace{3pt}}c@{\hspace{6pt}}|@{\hspace{6pt}}cc@{\hspace{3pt}}c}
212	\toprule
213	 & \multicolumn{3}{c}{Mistral-7B} & \multicolumn{3}{c}{LLaMA-8B} \\
214	 & KL & TEAL & Adv & KL & TEAL & Adv \\
215	\midrule
216	30\% & \textbf{6.77} & 8.38 & 1.24$\times$ & \textbf{8.96} & 10.97 & 1.22$\times$ \\ % exp_id: kl_30_mistral, teal_30_mistral, kl30_3seed_global
217	50\% & \textbf{8.65} & 18.31 & 2.12$\times$ & \textbf{11.79} & 23.31 & 1.98$\times$ \\ % exp_id: kl_50_mistral, teal_50_mistral
218	70\% & \textbf{13.33} & 61.72 & 4.63$\times$ & \textbf{17.91} & 100.11 & 5.59$\times$ \\ % exp_id: kl_70_mistral, teal_70_mistral
219	\bottomrule
220	\end{tabular}
221	\end{table}
222	
223	The KL advantage ratio is consistent across architectures (within 8\% at $\leq$50\% sparsity; 4.63$\times$ vs.\ 5.59$\times$ at 70\%) and provides preliminary evidence of generality at the 7--8B scale.
224	
225	\paragraph{Scale Generalization: Qwen-2.5-14B.}
226	\label{sec:14b}
227	Table~\ref{tab:14b} evaluates Qwen-2.5-14B~\cite{qwen2024qwen25} at 30\%: KL's PPL advantage generalizes ($1.47\times$ dense), but MMLU falls below TEAL/BCE (63.7 vs.\ 71.8\%), and uniform recovers only +0.8pp. The gap appears intrinsic to KL's output-preservation objective rather than allocation-induced. BCE collapses to 6.4\% native sparsity (\S\ref{sec:method:gradient}); Table~\ref{tab:14b} uses forced global top-$k$. % exp_id: qwen14b_kl30_s42, qwen14b_bce30_s42, qwen14b_bce30_s42_v2, qwen14b_teal30_eval, qwen14b_kl30_uniform, qwen14b_teal30_uniform
228	
229	\begin{table}[t]
230	\centering
231	\caption{Qwen-2.5-14B at 30\% sparsity. \textbf{Bold}: best sparse per column per group.}
232	\label{tab:14b}
233	\small
234	\begin{tabular}{lccccc}
235	\toprule
236	Method & PPL$\downarrow$ & ARC-c & WG & MMLU & GSM8K \\
237	\midrule
238	Dense & 5.19 & 67.58 & 81.06 & 79.77 & 87.57 \\
239	\midrule
240	\multicolumn{6}{l}{\emph{Global top-$k$ allocation}} \\
241	KL (Ours) & \textbf{7.62} & 57.17 & 72.06 & 63.72 & 48.82 \\ % exp_id: qwen14b_kl30_s42
242	TEAL & 8.73 & 56.83 & \textbf{72.69} & \textbf{71.83} & 49.51 \\ % exp_id: qwen14b_teal30_eval
243	BCE & 8.76 & \textbf{57.59} & 72.61 & 71.67 & \textbf{53.07} \\ % exp_id: qwen14b_bce30_s42_eval
244	\midrule
245	\multicolumn{6}{l}{\emph{Uniform allocation}} \\
246	KL (Ours) & \textbf{7.63} & 54.44 & \textbf{72.45} & 64.49 & --- \\ % exp_id: qwen14b_kl30_uniform
247	TEAL & 8.01 & \textbf{55.29} & 69.85 & \textbf{66.34} & --- \\ % exp_id: qwen14b_teal30_uniform
248	\bottomrule
249	\end{tabular}
250	\end{table}
251	
252	
253	\enlargethispage{8\baselineskip}
254	\paragraph{Inference Efficiency.}
255	The pipeline adds 6.4\% overhead while removing the compensation network ($-$2.7\% latency, $-$67.2M params; Appendix~\ref{app:latency}).
256	
257	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e067bc63-72dd-431c-9e9b-1c47dc14d751",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "fc5058d1-597a-4db6-8bf1-ed428e029cff",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\n\\paragraph{Model and Predictor.}\nWe evaluate on LLaMA-3.1-8B~\\cite{grattafiori2024llama3}, which uses SwiGLU FFN blocks~\\cite{shazeer2020glu} with $d_{\\text{model}}=4096$ and $d_{\\text{ff}}=14336$ across 32 layers.\nThe sparsity predictor is a two-layer MLP with 2.37M parameters per layer (75.9M total), implemented as Linear($4096 \\to 128$) + GELU + Linear($128 \\to 14336$), trained to produce per-neuron importance scores that minimize output-distribution divergence under sparsity.\n\n\\paragraph{Training.}\nAll predictors are trained for 1000 steps on WikiText-103 with sequence length 2048 and batch size 4, using AdamW~\\cite{loshchilov2019adamw} with learning rate $1 \\times 10^{-3}$, weight decay $5 \\times 10^{-2}$, and cosine decay.\nThe KL predictor uses Gumbel-Sigmoid relaxation~\\cite{jang2017gumbel} with temperature $\\tau=1.0$ annealed to $0.1$ over training.\n\n\\paragraph{Evaluation.}\nWe report perplexity on WikiText-2~\\cite{merity2017pointer} (seq\\_len=2048) and downstream accuracy on ARC-Challenge (25-shot), WinoGrande (5-shot), MMLU (5-shot), and GSM8K (8-shot).\n\n\\paragraph{Inference Protocol.}\nAt inference, the predictor produces per-neuron scores that are passed to TEAL's global top-$k$ allocation mechanism~\\cite{liu2025teal}, which distributes the sparsity budget across layers non-uniformly.\nWe term this \\textit{predictor-TEAL}: the predictor replaces TEAL's magnitude-based scoring while retaining its allocation strategy.\n\n\\paragraph{Baselines.}\nWe compare against: (1) \\textbf{Vanilla TEAL}~\\cite{liu2025teal}, which uses activation magnitudes directly; (2) \\textbf{BCE predictor} (DejaVu-style~\\cite{liu2023dejavu}), trained with per-neuron binary cross-entropy on magnitude-based oracle masks for 1000 and 2700 steps; (3) \\textbf{Uniform allocation}, which distributes the sparsity budget equally across layers; and (4) \\textbf{WINA}~\\cite{liu2025teal}, an importance-weighted variant.\n\n\n\\subsection{Main Results}\n\nTable~\\ref{tab:main} presents the primary comparison. We recommend uniform allocation for deployment (best downstream preservation); global allocation is analyzed to understand allocation-quality tradeoffs (\\S\\ref{sec:scaling}).\nAt 30\\% sparsity, KL distillation with global TEAL allocation achieves PPL 8.96$\\pm$0.02 (3-seed) and reduces TEAL's degradation from dense (10.97 $\\to$ 8.96, an 18\\% improvement). % exp_id: kl30_3seed_global\nThe advantage holds across additional downstream benchmarks (Appendix~\\ref{app:downstream}).\nUniform allocation at 30\\% provides stable downstream performance (MMLU 40.7$\\pm$1.3\\%, 3-seed) while global top-$k$ exhibits high seed variance (35.7$\\pm$9.5\\%), with late-layer starvation (L31 retention 28.4\\%) interacting with predictor initialization (\\S\\ref{sec:scaling}). % exp_id: bench_kl30_uniform, kl30_3seed\n\nAt 50\\% sparsity, KL distillation over vanilla TEAL widens the PPL advantage: 11.79 vs.\\ 23.31, a 49\\% reduction. % exp_id: bench_kl50_global, bench_teal50\nThe predictor generalizes to C4 validation at both 30\\% (PPL 16.03$\\pm$0.01, 2-seed) and 50\\% (52.5\\% over TEAL; Appendix~\\ref{app:ood}).\nHowever, all methods exhibit downstream collapse on MMLU (28.1$\\pm$0.2\\% vs.\\ 28.0$\\pm$0.6\\%, both $\\approx$ random, 3-seed) and GSM8K ($<$2.2\\%); this is a capacity-limited regime where no allocation strategy can recover. % exp_id: bench_kl50_global, d030_kl50_uniform, multi_seed_kl50_global\n\n\\begin{table}[t]\n\\centering\n\\caption{Main results on LLaMA-3.1-8B. PPL$\\downarrow$ on WikiText-2; accuracy$\\uparrow$ on downstream tasks. \\textbf{Bold}: best among compensation-free methods per sparsity level. BCE follows the DejaVu~\\cite{liu2023dejavu} predictor pipeline (per-neuron BCE on magnitude oracles) with a FastForward-style~\\cite{gautam2026fastforward} compensation network (67.2M params) applied post-masking; no TEAL allocation. Entries with $\\pm$ report 3-seed mean$\\pm$std ($s \\in \\{42, 123, 456\\}$); 50\\% uniform PPL is 3-seed ($11.92 \\pm 0.07$; Appendix~\\ref{app:stability}); remaining entries use seed 42.}\n\\label{tab:main}\n\\resizebox{\\columnwidth}{!}{\n\\begin{tabular}{llccccc}\n\\toprule\nSparsity & Method & PPL$\\downarrow$ & ARC-c & WG & MMLU & GSM8K \\\\\n\\midrule\n0\\% & Dense & 6.12 & 58.28 & 78.06 & 65.27 & 48.75 \\\\\n\\midrule\n\\multirow{3}{*}{30\\%}\n& TEAL vanilla & 10.97 & 42.32 & 66.06 & 38.61 & 7.88 \\\\ % exp_id: bench_teal30\n& KL global (Ours) & 8.96$\\pm$0.02 & \\textbf{43.8$\\pm$3.6} & \\textbf{70.2$\\pm$0.9} & 35.7$\\pm$9.5 & \\textbf{8.0$\\pm$0.7} \\\\ % exp_id: kl30_3seed_global\n& KL uniform & \\textbf{8.82} & 40.78 & 68.59 & \\textbf{40.7$\\pm$1.3} & 7.35 \\\\ % exp_id: kl30_3seed_uniform\n\\midrule\n\\multirow{4}{*}{50\\%}\n& TEAL vanilla & 23.31 & 28.41 & 53.04 & \\textbf{28.32} & 1.97 \\\\ % exp_id: bench_teal50\n& KL global (Ours) & \\textbf{11.79} & \\textbf{32.85} & \\textbf{63.46} & 28.1$\\pm$0.2 & 1.29 \\\\ % exp_id: multi_seed_kl50_global\n& KL uniform & 11.96 & 32.76 & 62.90 & 28.0$\\pm$0.6 & \\textbf{2.12} \\\\ % exp_id: multi_seed_kl50_uniform\n& BCE (2700 steps)$^\\ast$ & 28.13$\\pm$0.20 & 27.6$\\pm$0.6 & 51.8$\\pm$0.6 & 26.1$\\pm$0.5 & 2.1$\\pm$0.2 \\\\ % exp_id: bce50_3seed\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\subsection{Extended Training Analysis}\n\\label{sec:isocompute}\n\nTo test whether BCE simply requires more compute, we train it for 2700 steps (2.71$\\times$ the KL step budget, approximately equal wall-clock time: $\\sim$46 min BCE vs.\\ $\\sim$45 min KL on RTX PRO 6000).\nThe BCE predictor achieves PPL 28.13$\\pm$0.20 (3-seed), still 2.39$\\times$ worse than KL at 1000 steps (PPL 11.79). % exp_id: bce50_3seed\nThe difference is systematic, not due to architectural or compute limitations: both predictors use identical architectures and TEAL allocation, yet BCE achieves +7pp oracle F1 (0.613 vs.\\ 0.540) with 139\\% worse PPL (28.13 vs.\\ 11.79). KL's near-random precision (0.51) is consistent with learning a mask optimized for distributional fidelity rather than magnitude matching. % exp_id: f1_oracle_analysis, bce_isocompute_s42\nCoupled training correlates with better output preservation, but disentangling gradient coupling from oracle quality remains open (BCE uses magnitude oracles while KL optimizes output directly; an ablation using KL-derived masks as BCE targets would isolate the effect).\n\n\n\\subsection{Ablation Studies}\n\nTable~\\ref{tab:ablation} isolates the contribution of each design choice at 50\\% sparsity.\n\n\\begin{table}[t]\n\\centering\n\\caption{Ablation at 50\\% sparsity on LLaMA-3.1-8B (WikiText-2 PPL$\\downarrow$, unified benchmark protocol).}\n\\label{tab:ablation}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\nConfiguration & PPL$\\downarrow$ & $\\Delta$ from Ours \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{KL-based variants}} \\\\\nForward KL + Gumbel (Ours) & \\textbf{11.79} & --- \\\\ % exp_id: bench_kl50_global\nJSD (symmetric) + Gumbel & 12.54 & +0.75 \\\\ % exp_id: jsd_ablation_s42\nReverse KL + Gumbel & 12.80 & +1.01 \\\\ % exp_id: reverse_kl_ablation_s42\nForward KL + STE & 15.77 & +3.98 \\\\ % exp_id: ste_baseline_s42\n\\midrule\n\\multicolumn{3}{l}{\\textit{BCE-based variants}} \\\\\nBCE + Compensation (hard mask) & 25.44 & +13.65 \\\\ % exp_id: bce_comp_staged_s42\nBCE (no compensation) & 27.97 & +16.18 \\\\ % exp_id: eval_bce_v3_s42\nBCE + Gumbel + Penalty (no KL) & 38.02 & +26.23 \\\\ % exp_id: bce_gumbel_lagrangian_isolation\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Gumbel vs.\\ STE.}\nReplacing Gumbel-Sigmoid with STE~\\cite{bengio2013ste} degrades PPL from 11.79 to 15.77 (+3.98), accounting for 34.5\\% of the improvement over vanilla TEAL. % exp_id: ste_baseline_s42\n\n\\paragraph{Divergence Direction.}\nForward KL (mode-covering) outperforms JSD (+6.4\\%) and reverse KL (+8.6\\%), consistent with the SNR analysis in \\S\\ref{sec:method:gradient}: complete teacher supervision is associated with better global allocation quality. % exp_id: jsd_ablation_s42, reverse_kl_ablation_s42\nThis contrasts with MiniLLM~\\cite{gu2024minillm} (reverse KL for generation); in mask prediction, mode-covering ensures no important neuron is omitted.\n\n\\paragraph{SPON Contribution.}\nAdding SPON~\\cite{xu2026spon} bias correction reduces PPL from 12.08 to 11.79 (2.4\\% relative); see \\S\\ref{sec:spon} for decomposition.\\footnote{SPON analysis uses \\texttt{evaluate.py}; main results use the unified benchmark.} % exp_id: spon_2048_s42, mvp_kl_norm_v2_s42\n\n\\paragraph{Loss Function Isolation.}\nBCE with identical Gumbel-Sigmoid and penalty yields PPL 38.02, worse than vanilla BCE (27.97): the penalty interferes with per-neuron optimization without global coordination. % exp_id: bce_gumbel_lagrangian_isolation\nThe loss effect ($\\Delta$PPL=26.23) is $6.6\\times$ the relaxation effect ($\\Delta$PPL=3.98).\n\n\\paragraph{Compensation Redundancy.}\nAdding compensation~\\cite{gautam2026fastforward} (+67.2M params) to KL provides no benefit at either tested sparsity: at 50\\%, all five metrics are identical to KL-only; at 30\\%, PPL 8.97$\\pm$0.01 vs.\\ 8.96$\\pm$0.03 (2-seed). BCE requires compensation (27.97$\\to$25.44), yet remains $2.16\\times$ worse than KL without it. Training converges by step 700 (Appendix~\\ref{app:comp_convergence}). % exp_id: kl_comp_30_s42, kl_comp_30_s456, kl_comp_50_s42, bce_comp_staged_s42\n\n\\paragraph{Hyperparameter Robustness.}\nAppendix~\\ref{app:db_sensitivity} confirms robustness to predictor capacity ($d_b$, $<$3\\%), temperature ($<$1.8\\%), and training steps (saturated by 800). % exp_id: db_sensitivity_sweep, tau_schedule_sweep, training_steps_sweep\n\n\n\\subsection{Sparsity Scaling and Regime Analysis}\n\\label{sec:scaling}\n\nTable~\\ref{tab:scaling} and Figure~\\ref{fig:sparsity_sweep} show PPL as a function of sparsity for the KL predictor under global allocation and vanilla TEAL.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig2_sparsity_sweep.pdf}\n\\caption{Perplexity scaling with sparsity. The KL predictor's advantage grows disproportionately as more neurons are pruned.}\n\\label{fig:sparsity_sweep}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\caption{PPL scaling with sparsity (WikiText-2). KL advantage grows disproportionately with sparsity.}\n\\label{tab:scaling}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nSparsity & KL (Ours) & TEAL vanilla & Relative advantage \\\\\n\\midrule\n30\\% & \\textbf{8.96} & 10.97 & 18\\% \\\\ % exp_id: kl30_3seed_global\n50\\% & \\textbf{11.79} & 23.31 & 49\\% \\\\ % exp_id: bench_kl50_global\n70\\% & \\textbf{17.91} & 100.11 & 82\\% \\\\ % exp_id: kl_70_global_teal\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe KL advantage grows from 18\\% at 30\\% to 82\\% at 70\\%, where TEAL collapses (PPL 100.11) while the learned predictor maintains coherent allocation.\nIn absolute terms, KL/Dense degradation is $1.47\\times$ at 30\\%, $1.93\\times$ at 50\\%, and $2.93\\times$ at 70\\%, compared to TEAL/Dense ratios of $1.79\\times$, $3.81\\times$, and $16.4\\times$ respectively.\n\n\\paragraph{Three Operating Regions.}\nTable~\\ref{tab:phase} presents global vs.\\ uniform allocation at three sparsity levels and reveals qualitative shifts in allocation preference. Denser sampling (e.g., 35\\% sparsity) would be needed to precisely locate region boundaries.\n\n\\begin{table}[t]\n\\centering\n\\caption{Allocation analysis: global (TEAL) vs.\\ uniform per-layer allocation across sparsity levels. Entries with $\\pm$ report 3-seed mean$\\pm$std; remaining entries use seed 42. Each row uses a predictor trained at the respective sparsity target.}\n\\label{tab:phase}\n\\resizebox{\\columnwidth}{!}{\n\\begin{tabular}{llccccc}\n\\toprule\nSparsity & Allocation & PPL$\\downarrow$ & ARC-c & WG & MMLU & GSM8K \\\\\n\\midrule\n0\\% & Dense & 6.12 & 58.28 & 78.06 & 65.27 & 48.75 \\\\\n\\midrule\n\\multirow{3}{*}{30\\%}\n& TEAL vanilla & 10.97 & 42.32 & 66.06 & 38.61 & 7.88 \\\\ % exp_id: bench_teal30\n& KL global & 8.96$\\pm$0.02 & \\textbf{43.8$\\pm$3.6} & \\textbf{70.2$\\pm$0.9} & 35.7$\\pm$9.5 & \\textbf{8.0$\\pm$0.7} \\\\ % exp_id: kl30_3seed_global\n& KL uniform & \\textbf{8.82} & 40.78 & 68.59 & \\textbf{40.7$\\pm$1.3} & 7.35 \\\\ % exp_id: kl30_3seed_uniform\n\\midrule\n\\multirow{2}{*}{40\\%}\n& KL global & 10.12 & 40.96 & 65.35 & \\textbf{38.06} & \\textbf{5.00} \\\\ % exp_id: bench_kl40_global\n& KL uniform & \\textbf{8.36} & \\textbf{41.81} & \\textbf{67.17} & 30.68 & 3.94 \\\\ % exp_id: d030_kl40_uniform\n\\midrule\n\\multirow{3}{*}{50\\%}\n& TEAL vanilla & 23.31 & 28.41 & 53.04 & \\textbf{28.32} & 1.97 \\\\ % exp_id: bench_teal50\n& KL global & \\textbf{11.79} & \\textbf{32.85} & \\textbf{63.46} & 28.1$\\pm$0.2 & 1.29 \\\\ % exp_id: multi_seed_kl50_global\n& KL uniform & 11.96 & 32.76 & 62.90 & 28.0$\\pm$0.6 & \\textbf{2.12} \\\\ % exp_id: multi_seed_kl50_uniform\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThe allocation preference is \\emph{non-monotonic}. We observe three qualitative behaviors at the sampled sparsity levels (7--8B scale):\n\n\\noindent\\textbf{Budget-surplus ($\\leq$30\\%).}\nUniform allocation provides $7.5\\times$ smaller cross-seed MMLU standard deviation ($\\sigma$: 1.3pp vs.\\ 9.5pp), eliminating catastrophic seed-dependent degradation under global top-$k$ (MMLU 35.7$\\pm$9.5\\% vs.\\ 40.7$\\pm$1.3\\%, 3-seed). Vanilla TEAL is deterministic (magnitude-based) and exhibits zero cross-seed variance; the observed instability arises from the interaction between learned predictor initialization and global top-$k$'s layer-budget distribution, not from the distillation objective itself (PPL cross-seed CV $<$ 0.3\\%).\nGlobal top-$k$ starves late layers (L31: 28.4\\%, std/mean$=$1.89), and this starvation interacts unpredictably with predictor initialization (Appendix~\\ref{app:lagrangian}). % exp_id: kl30_3seed\n\n\\noindent\\textbf{Budget-constrained ($\\sim$40\\%).}\nThe preference reverses: global achieves MMLU 38.06\\% vs.\\ uniform's 30.68\\% (+7.4pp). % exp_id: bench_kl40_global, d030_kl40_uniform\nPPL remains low (8.36) but downstream accuracy degrades; PPL is a poor proxy for reasoning.\n\n\\noindent\\textbf{Capacity-limited ($\\geq$50\\%).}\nGlobal/uniform gap vanishes (MMLU 28.1$\\pm$0.2\\% vs.\\ 28.0$\\pm$0.6\\%, $\\sigma\\leq$0.6pp; contrast 9.5pp at 30\\%), consistent with capacity limitation. % exp_id: multi_seed_kl50_global, multi_seed_kl50_uniform\nLate-layer starvation persists across levels (L24--31 retention: 50.1/34.2/22.6\\% at 30/50/70\\% sparsity; Figure~\\ref{fig:retention}), consistent on both 7--8B models (\\S\\ref{sec:cross_arch}).\nUnder uniform allocation, 53\\% of the Dense$\\to$KL gap is predictor approximation vs.\\ 47\\% budget allocation (Appendix~\\ref{app:db_sensitivity}).\n\n\n\\subsection{SPON Orthogonality Analysis}\n\\label{sec:spon}\n\nAt 50\\% sparsity, the predictor's hidden-state perturbation (L2=482.65) and SPON's additive correction (L2=76.2, cosine similarity 0.196) are weakly correlated ($R^2$=0.038); SPON yields only 2.4\\% PPL improvement (12.08$\\to$11.79); the KL predictor already captures most recoverable signal. % exp_id: spon_decomposition, spon_2048_s42, mvp_kl_norm_v2_s42\n\n\\paragraph{Cross-Architecture Validation.}\n\\label{sec:cross_arch}\nTable~\\ref{tab:cross_arch} evaluates on Mistral-7B-v0.3~\\cite{jiang2023mistral} (GQA + sliding window, dense PPL 5.52).\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-architecture comparison (WikiText-2 PPL$\\downarrow$). Adv = TEAL\\,/\\,KL ratio. LLaMA uses global top-$k$; Mistral uses uniform allocation (matched within each architecture).}\n\\label{tab:cross_arch}\n\\small\n\\begin{tabular}{l@{\\hspace{4pt}}cc@{\\hspace{3pt}}c@{\\hspace{6pt}}|@{\\hspace{6pt}}cc@{\\hspace{3pt}}c}\n\\toprule\n & \\multicolumn{3}{c}{Mistral-7B} & \\multicolumn{3}{c}{LLaMA-8B} \\\\\n & KL & TEAL & Adv & KL & TEAL & Adv \\\\\n\\midrule\n30\\% & \\textbf{6.77} & 8.38 & 1.24$\\times$ & \\textbf{8.96} & 10.97 & 1.22$\\times$ \\\\ % exp_id: kl_30_mistral, teal_30_mistral, kl30_3seed_global\n50\\% & \\textbf{8.65} & 18.31 & 2.12$\\times$ & \\textbf{11.79} & 23.31 & 1.98$\\times$ \\\\ % exp_id: kl_50_mistral, teal_50_mistral\n70\\% & \\textbf{13.33} & 61.72 & 4.63$\\times$ & \\textbf{17.91} & 100.11 & 5.59$\\times$ \\\\ % exp_id: kl_70_mistral, teal_70_mistral\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe KL advantage ratio is consistent across architectures (within 8\\% at $\\leq$50\\% sparsity; 4.63$\\times$ vs.\\ 5.59$\\times$ at 70\\%) and provides preliminary evidence of generality at the 7--8B scale.\n\n\\paragraph{Scale Generalization: Qwen-2.5-14B.}\n\\label{sec:14b}\nTable~\\ref{tab:14b} evaluates Qwen-2.5-14B~\\cite{qwen2024qwen25} at 30\\%: KL's PPL advantage generalizes ($1.47\\times$ dense), but MMLU falls below TEAL/BCE (63.7 vs.\\ 71.8\\%), and uniform recovers only +0.8pp. The gap appears intrinsic to KL's output-preservation objective rather than allocation-induced. BCE collapses to 6.4\\% native sparsity (\\S\\ref{sec:method:gradient}); Table~\\ref{tab:14b} uses forced global top-$k$. % exp_id: qwen14b_kl30_s42, qwen14b_bce30_s42, qwen14b_bce30_s42_v2, qwen14b_teal30_eval, qwen14b_kl30_uniform, qwen14b_teal30_uniform\n\n\\begin{table}[t]\n\\centering\n\\caption{Qwen-2.5-14B at 30\\% sparsity. \\textbf{Bold}: best sparse per column per group.}\n\\label{tab:14b}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & PPL$\\downarrow$ & ARC-c & WG & MMLU & GSM8K \\\\\n\\midrule\nDense & 5.19 & 67.58 & 81.06 & 79.77 & 87.57 \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{Global top-$k$ allocation}} \\\\\nKL (Ours) & \\textbf{7.62} & 57.17 & 72.06 & 63.72 & 48.82 \\\\ % exp_id: qwen14b_kl30_s42\nTEAL & 8.73 & 56.83 & \\textbf{72.69} & \\textbf{71.83} & 49.51 \\\\ % exp_id: qwen14b_teal30_eval\nBCE & 8.76 & \\textbf{57.59} & 72.61 & 71.67 & \\textbf{53.07} \\\\ % exp_id: qwen14b_bce30_s42_eval\n\\midrule\n\\multicolumn{6}{l}{\\emph{Uniform allocation}} \\\\\nKL (Ours) & \\textbf{7.63} & 54.44 & \\textbf{72.45} & 64.49 & --- \\\\ % exp_id: qwen14b_kl30_uniform\nTEAL & 8.01 & \\textbf{55.29} & 69.85 & \\textbf{66.34} & --- \\\\ % exp_id: qwen14b_teal30_uniform\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\enlargethispage{8\\baselineskip}\n\\paragraph{Inference Efficiency.}\nThe pipeline adds 6.4\\% overhead while removing the compensation network ($-$2.7\\% latency, $-$67.2M params; Appendix~\\ref{app:latency}).\n\n",
      "numLines": 257,
      "startLine": 1,
      "totalLines": 257
    }
  },
  "sourceToolAssistantUUID": "e067bc63-72dd-431c-9e9b-1c47dc14d751",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-18T12:25:00.248Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NNcVEofH6Q655bBS7JCStM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fc5058d1-597a-4db6-8bf1-ed428e029cff",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "dd3b5ff5-bece-473f-a28a-9e85c0c501de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 37 · 2026-05-18T12:25:00.256Z_

<details><summary>↩ Tool result · `toolu_01NNcVEofH6Q655bBS7JCStM`</summary>

```text
1	\section{Related Work}
2	
3	\paragraph{Training-Free Activation Sparsity.}
4	TEAL~\cite{liu2025teal} applies global top-$k$ selection by activation magnitude and achieves 40--50\% sparsity with no training cost.
5	CATS~\cite{lee2024cats} adapts per-layer thresholds for SiLU/SwiGLU activations; R-Sparse~\cite{zhang2025rsparse} predicts sparsity from rank-aware SVD projections; DIP~\cite{federici2025dip} combines dynamic input pruning with cache-aware masking; SparseInfer~\cite{shin2025sparseinfer} predicts activation sparsity patterns from attention outputs without additional training.
6	All training-free methods determine masks from fixed statistics or input-independent criteria, while our predictor generates \emph{input-dependent} masks trained to minimize output-distribution divergence.
7	
8	\paragraph{Predictor-Based Contextual Sparsity.}
9	DejaVu~\cite{liu2023dejavu} introduced learned sparsity predictors trained via BCE to classify each neuron independently.
10	ShadowLLM~\cite{akhauri2024shadowllm} uses attention-based routing with per-layer MSE supervision for intermediate coupling within each layer but without end-to-end gradient signal.
11	FastForward~\cite{gautam2026fastforward} adds a 67.2M-parameter compensation network using BCE for mask prediction, adding inference latency.
12	SVD-CSP~\cite{serbin2026svdcsp} compresses sparsity predictors via SVD decomposition for reduced predictor overhead.
13	PowerInfer~\cite{song2024powerinfer} exploits power-law activation frequencies for GPU--CPU scheduling.
14	MaskLLM~\cite{fang2024maskllm} also employs learnable masks with Gumbel relaxation and frozen weights, but targets N:M semi-structured \emph{weight} sparsity (2:4 patterns) via per-group categorical selection (Gumbel-Softmax), producing fixed masks independent of input tokens.
15	Both share the principle of frozen weights + learnable masks + KL training, but solve distinct optimization problems: MaskLLM finds optimal static N:M patterns within fixed groups, while we predict dynamic per-token masks under a global budget constraint.
16	The structural mismatch we characterize (per-neuron gradient decomposition vs.\ global top-$k$) does not arise in MaskLLM's per-group categorical setting, where N:M patterns eliminate cross-group budget competition.
17	All prior predictor-based methods use decomposed (BCE) or intermediate (MSE) objectives where each neuron's gradient is independent of other mask states.
18	Our contribution is primarily empirical: we observe that a coupled KL objective propagates gradients through all downstream layers and quantify when this matters for global allocation quality.
19	
20	\paragraph{Static Bias Correction.}
21	SPON~\cite{xu2026spon} learns input-independent bias vectors via closed-form KL minimization per layer, absorbed into weights at deployment.
22	Our method is fundamentally different: a per-token contextual predictor trained end-to-end across all layers, producing input-dependent masks.
23	SPON solves a static per-layer problem; we solve a global dynamic prediction problem. The two are weakly correlated (cosine similarity 0.196, $R^2$=0.038; \S\ref{sec:experiments}).
24	
25	\paragraph{Activation Function Engineering.}
26	ReLU Strikes Back~\cite{mirzadeh2024relu} replaces SiLU with ReLU for $>$90\% natural sparsity; TurboSparse~\cite{song2024turbosparse} and ProSparse~\cite{song2025prosparse} engineer extreme sparsity through activation modifications; the Sparsing Law~\cite{luo2024sparsinglaw} formalizes how activation density increases with training compute.
27	MiniTron~\cite{muralidharan2024minitron} combines structured pruning with distillation but modifies architecture permanently.
28	All require retraining or weight modification; our method is a plug-in predictor on \emph{unmodified} SwiGLU models.
29	
30	\paragraph{Weight Pruning, Distillation, and Routing.}
31	Wanda~\cite{sun2024wanda} and SparseGPT~\cite{frantar2023sparsegpt} produce static weight masks; Switch Transformers~\cite{fedus2022switch} and Mixture-of-Depths~\cite{raposo2024mod} achieve conditional computation through learned routing.
32	KL-based distillation~\cite{kim2016sequencekd,sanh2019distilbert,gu2024minillm,agarwal2024gkd} trains compact students; SparseLoRA~\cite{khaki2025sparselora} exploits contextual sparsity for fine-tuning.
33	We apply the KL principle to train a sparsity predictor on unmodified dense models, using Gumbel-Sigmoid sampling~\cite{maddison2017concrete,louizos2018l0} for differentiable discrete mask optimization.
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dd3b5ff5-bece-473f-a28a-9e85c0c501de",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "404bd385-490f-402f-ab79-0c6c6e3fbfb8",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/related_work.tex",
      "content": "\\section{Related Work}\n\n\\paragraph{Training-Free Activation Sparsity.}\nTEAL~\\cite{liu2025teal} applies global top-$k$ selection by activation magnitude and achieves 40--50\\% sparsity with no training cost.\nCATS~\\cite{lee2024cats} adapts per-layer thresholds for SiLU/SwiGLU activations; R-Sparse~\\cite{zhang2025rsparse} predicts sparsity from rank-aware SVD projections; DIP~\\cite{federici2025dip} combines dynamic input pruning with cache-aware masking; SparseInfer~\\cite{shin2025sparseinfer} predicts activation sparsity patterns from attention outputs without additional training.\nAll training-free methods determine masks from fixed statistics or input-independent criteria, while our predictor generates \\emph{input-dependent} masks trained to minimize output-distribution divergence.\n\n\\paragraph{Predictor-Based Contextual Sparsity.}\nDejaVu~\\cite{liu2023dejavu} introduced learned sparsity predictors trained via BCE to classify each neuron independently.\nShadowLLM~\\cite{akhauri2024shadowllm} uses attention-based routing with per-layer MSE supervision for intermediate coupling within each layer but without end-to-end gradient signal.\nFastForward~\\cite{gautam2026fastforward} adds a 67.2M-parameter compensation network using BCE for mask prediction, adding inference latency.\nSVD-CSP~\\cite{serbin2026svdcsp} compresses sparsity predictors via SVD decomposition for reduced predictor overhead.\nPowerInfer~\\cite{song2024powerinfer} exploits power-law activation frequencies for GPU--CPU scheduling.\nMaskLLM~\\cite{fang2024maskllm} also employs learnable masks with Gumbel relaxation and frozen weights, but targets N:M semi-structured \\emph{weight} sparsity (2:4 patterns) via per-group categorical selection (Gumbel-Softmax), producing fixed masks independent of input tokens.\nBoth share the principle of frozen weights + learnable masks + KL training, but solve distinct optimization problems: MaskLLM finds optimal static N:M patterns within fixed groups, while we predict dynamic per-token masks under a global budget constraint.\nThe structural mismatch we characterize (per-neuron gradient decomposition vs.\\ global top-$k$) does not arise in MaskLLM's per-group categorical setting, where N:M patterns eliminate cross-group budget competition.\nAll prior predictor-based methods use decomposed (BCE) or intermediate (MSE) objectives where each neuron's gradient is independent of other mask states.\nOur contribution is primarily empirical: we observe that a coupled KL objective propagates gradients through all downstream layers and quantify when this matters for global allocation quality.\n\n\\paragraph{Static Bias Correction.}\nSPON~\\cite{xu2026spon} learns input-independent bias vectors via closed-form KL minimization per layer, absorbed into weights at deployment.\nOur method is fundamentally different: a per-token contextual predictor trained end-to-end across all layers, producing input-dependent masks.\nSPON solves a static per-layer problem; we solve a global dynamic prediction problem. The two are weakly correlated (cosine similarity 0.196, $R^2$=0.038; \\S\\ref{sec:experiments}).\n\n\\paragraph{Activation Function Engineering.}\nReLU Strikes Back~\\cite{mirzadeh2024relu} replaces SiLU with ReLU for $>$90\\% natural sparsity; TurboSparse~\\cite{song2024turbosparse} and ProSparse~\\cite{song2025prosparse} engineer extreme sparsity through activation modifications; the Sparsing Law~\\cite{luo2024sparsinglaw} formalizes how activation density increases with training compute.\nMiniTron~\\cite{muralidharan2024minitron} combines structured pruning with distillation but modifies architecture permanently.\nAll require retraining or weight modification; our method is a plug-in predictor on \\emph{unmodified} SwiGLU models.\n\n\\paragraph{Weight Pruning, Distillation, and Routing.}\nWanda~\\cite{sun2024wanda} and SparseGPT~\\cite{frantar2023sparsegpt} produce static weight masks; Switch Transformers~\\cite{fedus2022switch} and Mixture-of-Depths~\\cite{raposo2024mod} achieve conditional computation through learned routing.\nKL-based distillation~\\cite{kim2016sequencekd,sanh2019distilbert,gu2024minillm,agarwal2024gkd} trains compact students; SparseLoRA~\\cite{khaki2025sparselora} exploits contextual sparsity for fine-tuning.\nWe apply the KL principle to train a sparsity predictor on unmodified dense models, using Gumbel-Sigmoid sampling~\\cite{maddison2017concrete,louizos2018l0} for differentiable discrete mask optimization.\n",
      "numLines": 34,
      "startLine": 1,
      "totalLines": 34
    }
  },
  "sourceToolAssistantUUID": "dd3b5ff5-bece-473f-a28a-9e85c0c501de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-18T12:25:00.714Z_

<details open><summary>🔧 Tool call — Read · `toolu_01USsqYs8yQjZBnB6471id4g`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "404bd385-490f-402f-ab79-0c6c6e3fbfb8",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "28fb391c-f3df-475a-9906-b92ce724bb5c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 39 · 2026-05-18T12:25:00.719Z_

<details><summary>↩ Tool result · `toolu_01USsqYs8yQjZBnB6471id4g`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	\vspace{-2pt}
4	
5	A $<$1\% predictor with KL distillation halves TEAL's PPL across 7--14B; uniform allocation cuts cross-seed $\sigma$ $7.5\times$.
6	
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "28fb391c-f3df-475a-9906-b92ce724bb5c",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "40402f4f-f312-46a3-8d50-12c7bb5fc660",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\\vspace{-2pt}\n\nA $<$1\\% predictor with KL distillation halves TEAL's PPL across 7--14B; uniform allocation cuts cross-seed $\\sigma$ $7.5\\times$.\n\n",
      "numLines": 7,
      "startLine": 1,
      "totalLines": 7
    }
  },
  "sourceToolAssistantUUID": "28fb391c-f3df-475a-9906-b92ce724bb5c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-18T12:25:01.193Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NX3dUrfaZXnnTmDhSpA29o`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "40402f4f-f312-46a3-8d50-12c7bb5fc660",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "8f7509ec-a14c-4e2b-995e-1a2f9ff75fe6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 41 · 2026-05-18T12:25:01.197Z_

<details><summary>↩ Tool result · `toolu_01NX3dUrfaZXnnTmDhSpA29o`</summary>

```text
1	\section*{Limitations}
2	
3	Our primary evaluation uses WikiText-2 perplexity, and downstream benchmarks reveal that perplexity is a poor proxy for reasoning ability at moderate sparsity: 40\% sparsity achieves PPL 8.36 but MMLU already degrades, motivating 30\% as the recommended operating point for downstream fidelity.
4	Training requires 1000 steps on WikiText-103 ($\sim$45 minutes on RTX PRO 6000 for KL, $\sim$17 minutes for BCE), but a separate predictor must be trained for each sparsity target.
5	Our recommended operating point (30\% sparsity, uniform allocation) is validated at 7--8B scale; at 14B (Qwen-2.5-14B), KL's PPL advantage persists but the MMLU gap relative to TEAL/BCE is not resolved by uniform allocation (+0.8pp vs.\ +5.0pp at 8B), suggesting that KL's output-preservation objective may underweight task-specific features at higher knowledge densities. Scaling to 70B remains untested.
6	Out-of-distribution evaluation (Appendix~\ref{app:ood}) covers 30\% and 50\% sparsity on C4; extending to 70\% is left to future work.
7	Our attribution of KL's advantage to gradient coupling (\S\ref{sec:method:gradient}) is supported by SNR measurements and the BCE isolation ablation, but does not fully disentangle coupling from oracle quality: BCE uses magnitude-based oracles while KL directly optimizes output preservation, and an ablation using KL-derived masks as BCE targets would more precisely isolate the coupling effect.
8	At 30\% sparsity, global allocation exhibits 9.5pp cross-seed MMLU standard deviation (3-seed); allocation strategy interacts with predictor initialization in task-specific ways. This variance is MMLU-specific, as ARC, WinoGrande, and GSM8K show stable performance across seeds under both allocation strategies.
9	While we motivate our work with inference speedup potential, actual wall-clock acceleration depends on sparse kernel implementations (e.g., Triton, cuSPARSE) and hardware-specific memory access patterns; this work focuses on prediction quality rather than systems optimization.
10	Future directions include N:M structured sparsity for hardware-native acceleration, scaling to 13B+ models, and training a single predictor that serves multiple sparsity targets simultaneously.
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8f7509ec-a14c-4e2b-995e-1a2f9ff75fe6",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "2e9c5612-4b2d-491d-879c-2fa699306c10",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/limitations.tex",
      "content": "\\section*{Limitations}\n\nOur primary evaluation uses WikiText-2 perplexity, and downstream benchmarks reveal that perplexity is a poor proxy for reasoning ability at moderate sparsity: 40\\% sparsity achieves PPL 8.36 but MMLU already degrades, motivating 30\\% as the recommended operating point for downstream fidelity.\nTraining requires 1000 steps on WikiText-103 ($\\sim$45 minutes on RTX PRO 6000 for KL, $\\sim$17 minutes for BCE), but a separate predictor must be trained for each sparsity target.\nOur recommended operating point (30\\% sparsity, uniform allocation) is validated at 7--8B scale; at 14B (Qwen-2.5-14B), KL's PPL advantage persists but the MMLU gap relative to TEAL/BCE is not resolved by uniform allocation (+0.8pp vs.\\ +5.0pp at 8B), suggesting that KL's output-preservation objective may underweight task-specific features at higher knowledge densities. Scaling to 70B remains untested.\nOut-of-distribution evaluation (Appendix~\\ref{app:ood}) covers 30\\% and 50\\% sparsity on C4; extending to 70\\% is left to future work.\nOur attribution of KL's advantage to gradient coupling (\\S\\ref{sec:method:gradient}) is supported by SNR measurements and the BCE isolation ablation, but does not fully disentangle coupling from oracle quality: BCE uses magnitude-based oracles while KL directly optimizes output preservation, and an ablation using KL-derived masks as BCE targets would more precisely isolate the coupling effect.\nAt 30\\% sparsity, global allocation exhibits 9.5pp cross-seed MMLU standard deviation (3-seed); allocation strategy interacts with predictor initialization in task-specific ways. This variance is MMLU-specific, as ARC, WinoGrande, and GSM8K show stable performance across seeds under both allocation strategies.\nWhile we motivate our work with inference speedup potential, actual wall-clock acceleration depends on sparse kernel implementations (e.g., Triton, cuSPARSE) and hardware-specific memory access patterns; this work focuses on prediction quality rather than systems optimization.\nFuture directions include N:M structured sparsity for hardware-native acceleration, scaling to 13B+ models, and training a single predictor that serves multiple sparsity targets simultaneously.\n",
      "numLines": 11,
      "startLine": 1,
      "totalLines": 11
    }
  },
  "sourceToolAssistantUUID": "8f7509ec-a14c-4e2b-995e-1a2f9ff75fe6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 42 · 2026-05-18T12:25:02.129Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XDmCsfXXk6QwfrXTj1FwnS`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/ethics.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2e9c5612-4b2d-491d-879c-2fa699306c10",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "f19507f7-0707-4465-ab15-d248cab01572",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 43 · 2026-05-18T12:25:02.135Z_

<details><summary>↩ Tool result · `toolu_01XDmCsfXXk6QwfrXTj1FwnS`</summary>

```text
1	\section*{Ethics Statement}
2	
3	This work proposes a training method for sparsity predictors in pretrained language models, evaluated on publicly available models (LLaMA-3.1-8B, Mistral-7B-v0.3) and standard benchmarks (WikiText-2, WikiText-103, C4, ARC, WinoGrande, MMLU, GSM8K).
4	No new data collection, annotation, or human subjects are involved.
5	The method does not alter model outputs beyond the sparsity-induced degradation we analyze; it introduces no new generation capabilities or safety risks beyond those inherent in the base models.
6	Compute requirements are modest (1000 training steps, $\sim$45 minutes on a single GPU for KL training), presenting minimal environmental concern relative to the pretrained models we evaluate on.
7	We release no model weights or user-facing systems; our contribution is analytical (understanding KL distillation for sparsity) rather than deployment-oriented.
8	
9	\section*{Responsible NLP Research Checklist}
10	
11	\paragraph{A. Limitations and Risks.}
12	\begin{itemize}[nosep,leftmargin=*]
13	\item[\textbf{A1.}] Limitations are discussed in the Limitations section. Key limitations: evaluation limited to 7--8B models; perplexity is an imperfect proxy for downstream quality; wall-clock speedup requires sparse kernel support not implemented here.
14	\item[\textbf{A2.}] No foreseeable risks specific to this work beyond those inherent in the base language models. The method does not enable new capabilities or applications.
15	\end{itemize}
16	
17	\paragraph{B. Scientific Artifacts.}
18	\begin{itemize}[nosep,leftmargin=*]
19	\item[\textbf{B1.}] Yes. All models (LLaMA-3.1-8B~\cite{grattafiori2024llama3}, Mistral-7B-v0.3~\cite{jiang2023mistral}), datasets (WikiText~\cite{merity2017pointer}, C4~\cite{raffel2020c4}), and methods (TEAL~\cite{liu2025teal}, SPON~\cite{xu2026spon}) are cited with original references.
20	\item[\textbf{B2.}] LLaMA-3.1 is released under the Llama 3.1 Community License; Mistral-7B under Apache 2.0. WikiText and C4 are publicly available research datasets. Our use is consistent with their intended purposes.
21	\item[\textbf{B3.}] N/A. We do not release new artifacts in this submission.
22	\item[\textbf{B4.}] N/A. No personally identifiable information or offensive content is involved.
23	\item[\textbf{B5.}] N/A. No new datasets created.
24	\item[\textbf{B6.}] N/A. No crowdsourced data.
25	\end{itemize}
26	
27	\paragraph{C. Computational Experiments.}
28	\begin{itemize}[nosep,leftmargin=*]
29	\item[\textbf{C1.}] Yes. Model sizes (8B base, 75.9M predictor), training compute (1000 steps, batch 4, seq 2048), optimizer (AdamW~\cite{loshchilov2019adamw}, lr=$10^{-3}$, cosine decay), and GPU (NVIDIA RTX PRO 6000 Blackwell for both training and latency measurement) are reported in \S4.1 and Appendix A.
30	\item[\textbf{C2.}] Yes. Hyperparameters are fully specified: bottleneck $d_b{=}128$, temperature schedule $\tau: 1.0 \to 0.1$, sparsity penalty parameters ($\epsilon{=}0.02$, $\lambda_{\max}$), weight decay $5{\times}10^{-2}$.
31	\item[\textbf{C3.}] Yes. Three-seed evaluation reported (PPL std=0.07, CV$<$1\%; Appendix E).
32	\item[\textbf{C4.}] Yes. All evaluation uses established metrics (perplexity, accuracy) on standard benchmarks with standard few-shot protocols (ARC 25-shot, WinoGrande 5-shot, MMLU 5-shot, GSM8K 8-shot).
33	\end{itemize}
34	
35	\paragraph{D. Human Subjects.}
36	\begin{itemize}[nosep,leftmargin=*]
37	\item[\textbf{D1--D5.}] N/A. No human subjects, crowdsourcing, or annotation involved.
38	\end{itemize}
39	
40	\paragraph{E. AI Assistants.}
41	\begin{itemize}[nosep,leftmargin=*]
42	\item[\textbf{E1.}] AI writing assistants were used for drafting and editing. All scientific claims, experimental results, and analyses were produced and verified by the authors.
43	\end{itemize}
44	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f19507f7-0707-4465-ab15-d248cab01572",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "45079a97-ea31-4539-bf4e-496e2625e3ac",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/ethics.tex",
      "content": "\\section*{Ethics Statement}\n\nThis work proposes a training method for sparsity predictors in pretrained language models, evaluated on publicly available models (LLaMA-3.1-8B, Mistral-7B-v0.3) and standard benchmarks (WikiText-2, WikiText-103, C4, ARC, WinoGrande, MMLU, GSM8K).\nNo new data collection, annotation, or human subjects are involved.\nThe method does not alter model outputs beyond the sparsity-induced degradation we analyze; it introduces no new generation capabilities or safety risks beyond those inherent in the base models.\nCompute requirements are modest (1000 training steps, $\\sim$45 minutes on a single GPU for KL training), presenting minimal environmental concern relative to the pretrained models we evaluate on.\nWe release no model weights or user-facing systems; our contribution is analytical (understanding KL distillation for sparsity) rather than deployment-oriented.\n\n\\section*{Responsible NLP Research Checklist}\n\n\\paragraph{A. Limitations and Risks.}\n\\begin{itemize}[nosep,leftmargin=*]\n\\item[\\textbf{A1.}] Limitations are discussed in the Limitations section. Key limitations: evaluation limited to 7--8B models; perplexity is an imperfect proxy for downstream quality; wall-clock speedup requires sparse kernel support not implemented here.\n\\item[\\textbf{A2.}] No foreseeable risks specific to this work beyond those inherent in the base language models. The method does not enable new capabilities or applications.\n\\end{itemize}\n\n\\paragraph{B. Scientific Artifacts.}\n\\begin{itemize}[nosep,leftmargin=*]\n\\item[\\textbf{B1.}] Yes. All models (LLaMA-3.1-8B~\\cite{grattafiori2024llama3}, Mistral-7B-v0.3~\\cite{jiang2023mistral}), datasets (WikiText~\\cite{merity2017pointer}, C4~\\cite{raffel2020c4}), and methods (TEAL~\\cite{liu2025teal}, SPON~\\cite{xu2026spon}) are cited with original references.\n\\item[\\textbf{B2.}] LLaMA-3.1 is released under the Llama 3.1 Community License; Mistral-7B under Apache 2.0. WikiText and C4 are publicly available research datasets. Our use is consistent with their intended purposes.\n\\item[\\textbf{B3.}] N/A. We do not release new artifacts in this submission.\n\\item[\\textbf{B4.}] N/A. No personally identifiable information or offensive content is involved.\n\\item[\\textbf{B5.}] N/A. No new datasets created.\n\\item[\\textbf{B6.}] N/A. No crowdsourced data.\n\\end{itemize}\n\n\\paragraph{C. Computational Experiments.}\n\\begin{itemize}[nosep,leftmargin=*]\n\\item[\\textbf{C1.}] Yes. Model sizes (8B base, 75.9M predictor), training compute (1000 steps, batch 4, seq 2048), optimizer (AdamW~\\cite{loshchilov2019adamw}, lr=$10^{-3}$, cosine decay), and GPU (NVIDIA RTX PRO 6000 Blackwell for both training and latency measurement) are reported in \\S4.1 and Appendix A.\n\\item[\\textbf{C2.}] Yes. Hyperparameters are fully specified: bottleneck $d_b{=}128$, temperature schedule $\\tau: 1.0 \\to 0.1$, sparsity penalty parameters ($\\epsilon{=}0.02$, $\\lambda_{\\max}$), weight decay $5{\\times}10^{-2}$.\n\\item[\\textbf{C3.}] Yes. Three-seed evaluation reported (PPL std=0.07, CV$<$1\\%; Appendix E).\n\\item[\\textbf{C4.}] Yes. All evaluation uses established metrics (perplexity, accuracy) on standard benchmarks with standard few-shot protocols (ARC 25-shot, WinoGrande 5-shot, MMLU 5-shot, GSM8K 8-shot).\n\\end{itemize}\n\n\\paragraph{D. Human Subjects.}\n\\begin{itemize}[nosep,leftmargin=*]\n\\item[\\textbf{D1--D5.}] N/A. No human subjects, crowdsourcing, or annotation involved.\n\\end{itemize}\n\n\\paragraph{E. AI Assistants.}\n\\begin{itemize}[nosep,leftmargin=*]\n\\item[\\textbf{E1.}] AI writing assistants were used for drafting and editing. All scientific claims, experimental results, and analyses were produced and verified by the authors.\n\\end{itemize}\n",
      "numLines": 44,
      "startLine": 1,
      "totalLines": 44
    }
  },
  "sourceToolAssistantUUID": "f19507f7-0707-4465-ab15-d248cab01572",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 44 · 2026-05-18T12:25:02.301Z_

<details open><summary>🔧 Tool call — Read · `toolu_012sr2Y6pMsob15zzbM2uUyu`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "45079a97-ea31-4539-bf4e-496e2625e3ac",
  "isSidechain": false,
  "requestId": "req_011CbA2gBcT68jL5qeyYHKWu",
  "type": "assistant",
  "uuid": "16514193-3cef-4483-82f3-9fff786a4267",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014kPGpKkVoQxJTFbx68JVVV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 402,
      "cache_creation_input_tokens": 710,
      "cache_read_input_tokens": 31425,
      "output_tokens": 799,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 710,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 402,
          "output_tokens": 799,
          "cache_read_input_tokens": 31425,
          "cache_creation_input_tokens": 710,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 710
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

_source line 45 · 2026-05-18T12:25:02.361Z_

```json
{
  "parentUuid": "19521a26-d77a-459a-b35c-0904a932a061",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "320c2634-5819-4985-b972-bb6421cfb8e4",
  "timestamp": "2026-05-18T12:25:02.361Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 46_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。  ## Venue 信息 - **目标**: EMNLP 2026 (ARR May 2026 cycle) - **截止日期**: 2026-05-25 - **格式**: ACL style, Long paper ≤8 页正文, double-blind - **评分标准*…",
  "leafUuid": "320c2634-5819-4985-b972-bb6421cfb8e4",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Runtime record

_source line 47_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Assistant

_source line 48 · 2026-05-18T12:25:04.774Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have the full paper. Let me also check the references file and verify them.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "320c2634-5819-4985-b972-bb6421cfb8e4",
  "isSidechain": false,
  "requestId": "req_011CbA2gogcZC7c56FBS52Re",
  "type": "assistant",
  "uuid": "bfdf97c7-e5e7-4eb9-9bbf-5d706a2ad65d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Wp8GvaSbGUh6LbJv25w73",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 46047,
      "cache_read_input_tokens": 11841,
      "output_tokens": 291,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 46047,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 291,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 46047,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 46047
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

_source line 49 · 2026-05-18T12:25:06.674Z_

已通读全文。现在验证引用，并获取 ACL ARR reviewer guidelines 的更多细节。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bfdf97c7-e5e7-4eb9-9bbf-5d706a2ad65d",
  "isSidechain": false,
  "requestId": "req_011CbA2gogcZC7c56FBS52Re",
  "type": "assistant",
  "uuid": "03f60c90-588d-4c33-8bbc-0f25100c05b4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Wp8GvaSbGUh6LbJv25w73",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 46047,
      "cache_read_input_tokens": 11841,
      "output_tokens": 291,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 46047,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 291,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 46047,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 46047
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

_source line 50 · 2026-05-18T12:25:08.591Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__verify_references · `toolu_01LVZTRVgxseFVCo9N3EQyiu`</summary>

```json
{
  "paper_dir": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper",
  "project": "distill_sparse_swiglu"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "03f60c90-588d-4c33-8bbc-0f25100c05b4",
  "isSidechain": false,
  "requestId": "req_011CbA2gogcZC7c56FBS52Re",
  "type": "assistant",
  "uuid": "83f1fcb5-fee7-42bc-9c5d-3efa2aa480a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Wp8GvaSbGUh6LbJv25w73",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 46047,
      "cache_read_input_tokens": 11841,
      "output_tokens": 291,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 46047,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 291,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 46047,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 46047
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

_source line 51 · 2026-05-18T12:25:10.943Z_

<details open><summary>🔧 Tool call — WebFetch · `toolu_01KhnaVvDKVP18cpibLALQ3U`</summary>

```json
{
  "url": "https://aclrollingreview.org/reviewerguidelines",
  "prompt": "Extract the complete reviewer guidelines: what reviewers should evaluate, how to score soundness and excitement, what counts as a strength vs weakness, guidance on experimental rigor, and any specific instructions about claims vs evidence."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "83f1fcb5-fee7-42bc-9c5d-3efa2aa480a3",
  "isSidechain": false,
  "requestId": "req_011CbA2gogcZC7c56FBS52Re",
  "type": "assistant",
  "uuid": "1a3eacba-d3e9-44ff-a597-eebc19989942",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Wp8GvaSbGUh6LbJv25w73",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 46047,
      "cache_read_input_tokens": 11841,
      "output_tokens": 291,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 46047,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 291,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 46047,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 46047
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

_source line 52 · 2026-05-18T12:25:42.581Z_

<details><summary>↩ Tool result · `toolu_01LVZTRVgxseFVCo9N3EQyiu`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 39, \"total_citations\": 76, \"unique_cited_keys\": 39, \"orphan_bib\": 0, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 35, \"online_not_found\": 0, \"online_mismatch\": 4}, \"cross_check\": {\"orphan_bib\": [], \"missing_bib\": [], \"orphan_count\": 0, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"fang2024maskllm\", \"type\": \"inproceedings\", \"title\": \"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\", \"authors\": \"Gongfan Fang and Hongxu Yin and Saurav Muralidharan and Greg Heinrich and Jeff P...\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems (NeurIPS)\"}, {\"key\": \"xu2026spon\", \"type\": \"inproceedings\", \"title\": \"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\", \"authors\": \"Haotian Xu and Jiannan Yang and Tian Gao and Tsui-Wei Weng and Tengfei Ma\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"muralidharan2024minitron\", \"type\": \"inproceedings\", \"title\": \"Compact Language Models via Pruning and Knowledge Distillation\", \"authors\": \"Saurav Muralidharan and Sharath Turuvekere Sreenivas and Raviraj Joshi and Marci...\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems (NeurIPS)\"}, {\"key\": \"gautam2026fastforward\", \"type\": \"article\", \"title\": \"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\", \"authors\": \"Aayush Gautam and Mukul Gagrani and Junyoung Park and Mingu Lee and Chiris Lott ...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2602.00397\"}, {\"key\": \"liu2025teal\", \"type\": \"inproceedings\", \"title\": \"Training-Free Activation Sparsity in Large Language Models\", \"authors\": \"James Liu and Pragaash Ponnusamy and Tianle Cai and Han Guo and Yoon Kim and Ben...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"liu2023dejavu\", \"type\": \"inproceedings\", \"title\": \"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\", \"authors\": \"Zichang Liu and Jue Wang and Tri Dao and Tianyi Zhou and Binhang Yuan and Zhao S...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"akhauri2024shadowllm\", \"type\": \"inproceedings\", \"title\": \"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\", \"authors\": \"Yash Akhauri and Ahmed F AbouElhamayed and Jordan Dotzel and Zhiru Zhang and Ale...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"lee2024cats\", \"type\": \"article\", \"title\": \"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\", \"authors\": \"Donghyun Lee and Je-Yong Lee and Genghan Zhang and Mo Tiwari and Azalia Mirhosei...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2404.08763\"}, {\"key\": \"zhang2025rsparse\", \"type\": \"inproceedings\", \"title\": \"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\", \"authors\": \"Zhenyu Zhang and Zechun Liu and Yuandong Tian and Harshit Khaitan and Zhangyang ...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"federici2025dip\", \"type\": \"inproceedings\", \"title\": \"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\", \"authors\": \"Marco Federici and Davide Belli and Mart van Baalen and Amir Jalalirad and Andri...\", \"year\": \"2024\", \"venue\": \"Proceedings of Machine Learning and Systems (MLSys)\"}, {\"key\": \"shin2025sparseinfer\", \"type\": \"inproceedings\", \"title\": \"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\", \"authors\": \"Jiho Shin and Hoeseok Yang and Youngmin Yi\", \"year\": \"2025\", \"venue\": \"Proceedings of the Design, Automation \\\\& Test in Europe Conference (DATE)\"}, {\"key\": \"serbin2026svdcsp\", \"type\": \"article\", \"title\": \"SVD Contextual Sparsity Predictors for Fast LLM Inference\", \"authors\": \"Georgii Serbin and Kirill Koshkin and Zhongao Sun and Anastasiya Bistrigova and ...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2603.14110\"}, {\"key\": \"mirzadeh2024relu\", \"type\": \"inproceedings\", \"title\": \"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\", \"authors\": \"Iman Mirzadeh and Keivan Alizadeh and Sachin Mehta and Carlo C Del Mundo and Onc...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"song2024turbosparse\", \"type\": \"article\", \"title\": \"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\", \"authors\": \"Yixin Song and Haotong Xie and Zhengyan Zhang and Bo Wen and Li Ma and Zeyu Mi a...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2406.05955\"}, {\"key\": \"song2025prosparse\", \"type\": \"inproceedings\", \"title\": \"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\", \"authors\": \"Chenyang Song and Xu Han and Zhengyan Zhang and Shengding Hu and Xiyu Shi and Ku...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Computational Linguistics (COLING...\"}, {\"key\": \"luo2024sparsinglaw\", \"type\": \"article\", \"title\": \"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\", \"authors\": \"Yuqi Luo and Chenyang Song and Xu Han and Yingfa Chen and Chaojun Xiao and Xiaoj...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2411.02335\"}, {\"key\": \"song2024powerinfer\", \"type\": \"inproceedings\", \"title\": \"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\", \"authors\": \"Yixin Song and Zeyu Mi and Haotong Xie and Haibo Chen\", \"year\": \"2024\", \"venue\": \"Proceedings of the ACM Symposium on Operating Systems Principles (SOSP)\"}, {\"key\": \"kim2016sequencekd\", \"type\": \"inproceedings\", \"title\": \"Sequence-Level Knowledge Distillation\", \"authors\": \"Yoon Kim and Alexander M. Rush\", \"year\": \"2016\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"gu2024minillm\", \"type\": \"inproceedings\", \"title\": \"MiniLLM: Knowledge Distillation of Large Language Models\", \"authors\": \"Yuxian Gu and Li Dong and Furu Wei and Minlie Huang\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"agarwal2024gkd\", \"type\": \"inproceedings\", \"title\": \"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\", \"authors\": \"Rishabh Agarwal and Nino Vieillard and Yongchao Zhou and Piotr Stanczyk and Sabe...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"khaki2025sparselora\", \"type\": \"inproceedings\", \"title\": \"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\", \"authors\": \"Samir Khaki and Xiuyu Li and Junxian Guo and Ligeng Zhu and Konstantinos N. Plat...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"raposo2024mod\", \"type\": \"article\", \"title\": \"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\", \"authors\": \"David Raposo and Sam Ritter and Blake Richards and Timothy Lillicrap and Peter C...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2404.02258\"}, {\"key\": \"sanh2019distilbert\", \"type\": \"article\", \"title\": \"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\", \"authors\": \"Victor Sanh and Lysandre Debut and Julien Chaumond and Thomas Wolf\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1910.01108\"}, {\"key\": \"sun2024wanda\", \"type\": \"inproceedings\", \"title\": \"A Simple and Effective Pruning Approach for Large Language Models\", \"authors\": \"Mingjie Sun and Zhuang Liu and Anna Bair and J. Zico Kolter\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"frantar2023sparsegpt\", \"type\": \"inproceedings\", \"title\": \"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\", \"authors\": \"Elias Frantar and Dan Alistarh\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"szatkowski2024d2dmoe\", \"type\": \"inproceedings\", \"title\": \"Exploiting Activation Sparsity with Dense to Dynamic-$k$ Mixture-of-Experts Conversion\", \"authors\": \"Filip Szatkowski and Bartosz W\\\\'ojcik and Miko\\\\laj Pi\\\\'orczy\\\\'nski and Simone Sc...\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems (NeurIPS)\"}, {\"key\": \"fedus2022switch\", \"type\": \"article\", \"title\": \"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\", \"authors\": \"William Fedus and Barret Zoph and Noam Shazeer\", \"year\": \"2022\", \"venue\": \"Journal of Machine Learning Research\"}, {\"key\": \"louizos2018l0\", \"type\": \"inproceedings\", \"title\": \"Learning Sparse Neural Networks through $L_0$ Regularization\", \"authors\": \"Christos Louizos and Max Welling and Diederik P. Kingma\", \"year\": \"2018\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"maddison2017concrete\", \"type\": \"inproceedings\", \"title\": \"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\", \"authors\": \"Chris J. Maddison and Andriy Mnih and Yee Whye Teh\", \"year\": \"2017\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"grattafiori2024llama3\", \"type\": \"article\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Aaron Grattafiori and Abhimanyu Dubey and Abhinav Jauhri and Abhinav Pandey and ...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2407.21783\"}, {\"key\": \"qwen2024qwen25\", \"type\": \"article\", \"title\": \"Qwen2.5 Technical Report\", \"authors\": \"Qwen Team\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2412.15115\"}, {\"key\": \"jiang2023mistral\", \"type\": \"article\", \"title\": \"Mistral 7B\", \"authors\": \"Albert Q. Jiang and Alexandre Sablayrolles and Arthur Mensch and Chris Bamford a...\", \"year\": \"2023\", \"venue\": \"arXiv preprint arXiv:2310.06825\"}, {\"key\": \"jang2017gumbel\", \"type\": \"inproceedings\", \"title\": \"Categorical Reparameterization with Gumbel-Softmax\", \"authors\": \"Eric Jang and Shixiang Gu and Ben Poole\", \"year\": \"2017\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"shazeer2020glu\", \"type\": \"article\", \"title\": \"GLU Variants Improve Transformer\", \"authors\": \"Noam Shazeer\", \"year\": \"2020\", \"venue\": \"arXiv preprint arXiv:2002.05202\"}, {\"key\": \"merity2017pointer\", \"type\": \"inproceedings\", \"title\": \"Pointer Sentinel Mixture Models\", \"authors\": \"Stephen Merity and Caiming Xiong and James Bradbury and Richard Socher\", \"year\": \"2017\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"hinton2015distilling\", \"type\": \"inproceedings\", \"title\": \"Distilling the Knowledge in a Neural Network\", \"authors\": \"Geoffrey Hinton and Oriol Vinyals and Jeff Dean\", \"year\": \"2015\", \"venue\": \"NeurIPS 2014 Deep Learning Workshop\"}, {\"key\": \"bengio2013ste\", \"type\": \"article\", \"title\": \"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\", \"authors\": \"Yoshua Bengio and Nicholas L\\\\'eonard and Aaron Courville\", \"year\": \"2013\", \"venue\": \"arXiv preprint arXiv:1308.3432\"}, {\"key\": \"loshchilov2019adamw\", \"type\": \"inproceedings\", \"title\": \"Decoupled Weight Decay Regularization\", \"authors\": \"Ilya Loshchilov and Frank Hutter\", \"year\": \"2019\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"raffel2020c4\", \"type\": \"article\", \"title\": \"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\", \"authors\": \"Colin Raffel and Noam Shazeer and Adam Roberts and Katherine Lee and Sharan Nara...\", \"year\": \"2020\", \"venue\": \"Journal of Machine Learning Research\"}], \"tex_citations\": [{\"key\": \"shazeer2020glu\", \"file\": \"introduction.tex\", \"line\": 3, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"introduction.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"introduction.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"jang2017gumbel\", \"file\": \"introduction.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"grattafiori2024llama3\", \"file\": \"introduction.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"jiang2023mistral\", \"file\": \"introduction.tex\", \"line\": 20, \"command\": \"cite\"}, {\"key\": \"qwen2024qwen25\", \"file\": \"introduction.tex\", \"line\": 20, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"related_work.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"lee2024cats\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"zhang2025rsparse\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"federici2025dip\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"shin2025sparseinfer\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"akhauri2024shadowllm\", \"file\": \"related_work.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"related_work.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"serbin2026svdcsp\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"song2024powerinfer\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"fang2024maskllm\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"related_work.tex\", \"line\": 21, \"command\": \"cite\"}, {\"key\": \"mirzadeh2024relu\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"song2024turbosparse\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"song2025prosparse\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"luo2024sparsinglaw\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"muralidharan2024minitron\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"sun2024wanda\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"frantar2023sparsegpt\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"fedus2022switch\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"raposo2024mod\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"kim2016sequencekd\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"sanh2019distilbert\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"gu2024minillm\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"agarwal2024gkd\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"khaki2025sparselora\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"maddison2017concrete\", \"file\": \"related_work.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"louizos2018l0\", \"file\": \"related_work.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"shazeer2020glu\", \"file\": \"method.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"method.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"jang2017gumbel\", \"file\": \"method.tex\", \"line\": 49, \"command\": \"cite\"}, {\"key\": \"bengio2013ste\", \"file\": \"method.tex\", \"line\": 62, \"command\": \"cite\"}, {\"key\": \"hinton2015distilling\", \"file\": \"method.tex\", \"line\": 80, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"method.tex\", \"line\": 175, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"akhauri2024shadowllm\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"szatkowski2024d2dmoe\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"method.tex\", \"line\": 183, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"method.tex\", \"line\": 184, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"method.tex\", \"line\": 184, \"command\": \"cite\"}, {\"key\": \"szatkowski2024d2dmoe\", \"file\": \"method.tex\", \"line\": 185, \"command\": \"cite\"}, {\"key\": \"grattafiori2024llama3\", \"file\": \"experiments.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"shazeer2020glu\", \"file\": \"experiments.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"loshchilov2019adamw\", \"file\": \"experiments.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"jang2017gumbel\", \"file\": \"experiments.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"merity2017pointer\", \"file\": \"experiments.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"experiments.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"experiments.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"experiments.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"experiments.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"experiments.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"experiments.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"bengio2013ste\", \"file\": \"experiments.tex\", \"line\": 99, \"command\": \"cite\"}, {\"key\": \"gu2024minillm\", \"file\": \"experiments.tex\", \"line\": 103, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"experiments.tex\", \"line\": 106, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"experiments.tex\", \"line\": 113, \"command\": \"cite\"}, {\"key\": \"jiang2023mistral\", \"file\": \"experiments.tex\", \"line\": 204, \"command\": \"cite\"}, {\"key\": \"qwen2024qwen25\", \"file\": \"experiments.tex\", \"line\": 227, \"command\": \"cite\"}, {\"key\": \"grattafiori2024llama3\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"jiang2023mistral\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"merity2017pointer\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"raffel2020c4\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"loshchilov2019adamw\", \"file\": \"ethics.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"raffel2020c4\", \"file\": \"appendix.tex\", \"line\": 154, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"appendix.tex\", \"line\": 235, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"fang2024maskllm\", \"title\": \"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"xu2026spon\", \"title\": \"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"muralidharan2024minitron\", \"title\": \"Compact Language Models via Pruning and Knowledge Distillation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Compact Language Models via Pruning and Knowledge Distillation\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gautam2026fastforward\", \"title\": \"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"liu2025teal\", \"title\": \"Training-Free Activation Sparsity in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Training-Free Activation Sparsity in Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"liu2023dejavu\", \"title\": \"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"akhauri2024shadowllm\", \"title\": \"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"lee2024cats\", \"title\": \"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"zhang2025rsparse\", \"title\": \"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"federici2025dip\", \"title\": \"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\", \"status\": \"verified\", \"confidence\": 0.893, \"matched_title\": \"Code Artifact for Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shin2025sparseinfer\", \"title\": \"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"serbin2026svdcsp\", \"title\": \"SVD Contextual Sparsity Predictors for Fast LLM Inference\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SVD Contextual Sparsity Predictors for Fast LLM Inference\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mirzadeh2024relu\", \"title\": \"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"song2024turbosparse\", \"title\": \"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"song2025prosparse\", \"title\": \"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"luo2024sparsinglaw\", \"title\": \"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"song2024powerinfer\", \"title\": \"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"kim2016sequencekd\", \"title\": \"Sequence-Level Knowledge Distillation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Sequence-Level Knowledge Distillation\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gu2024minillm\", \"title\": \"MiniLLM: Knowledge Distillation of Large Language Models\", \"status\": \"verified\", \"confidence\": 0.893, \"matched_title\": \"MiniLLM: On-Policy Distillation of Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"agarwal2024gkd\", \"title\": \"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"khaki2025sparselora\", \"title\": \"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=khaki vs api=samir\"], \"note\": \"\"}, {\"key\": \"raposo2024mod\", \"title\": \"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sanh2019distilbert\", \"title\": \"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sun2024wanda\", \"title\": \"A Simple and Effective Pruning Approach for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple and Effective Pruning Approach for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frantar2023sparsegpt\", \"title\": \"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"szatkowski2024d2dmoe\", \"title\": \"Exploiting Activation Sparsity with Dense to Dynamic-$k$ Mixture-of-Experts Conversion\", \"status\": \"verified\", \"confidence\": 0.988, \"matched_title\": \"Exploiting Activation Sparsity with Dense to Dynamic-k Mixture-of-Experts Conversion\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fedus2022switch\", \"title\": \"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"louizos2018l0\", \"title\": \"Learning Sparse Neural Networks through $L_0$ Regularization\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Learning Sparse Neural Networks through $L_0$ Regularization\", \"matched_year\": \"2017\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"maddison2017concrete\", \"title\": \"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"grattafiori2024llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"qwen2024qwen25\", \"title\": \"Qwen2.5 Technical Report\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Qwen2.5 Technical Report\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=team vs api=qwen\"], \"note\": \"\"}, {\"key\": \"jiang2023mistral\", \"title\": \"Mistral 7B\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mistral 7B\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"jang2017gumbel\", \"title\": \"Categorical Reparameterization with Gumbel-Softmax\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Categorical Reparameterization with Gumbel-Softmax\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shazeer2020glu\", \"title\": \"GLU Variants Improve Transformer\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLU Variants Improve Transformer\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"merity2017pointer\", \"title\": \"Pointer Sentinel Mixture Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Pointer Sentinel Mixture Models\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"hinton2015distilling\", \"title\": \"Distilling the Knowledge in a Neural Network\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Distilling the Knowledge in a Neural Network\", \"matched_year\": \"2015\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bengio2013ste\", \"title\": \"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\", \"matched_year\": \"2013\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"loshchilov2019adamw\", \"title\": \"Decoupled Weight Decay Regularization\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Decoupled Weight Decay Regularization\", \"matched_year\": \"2017\", \"mismatch_fields\": [\"year: bib=2019 vs api=2017\"], \"note\": \"\"}, {\"key\": \"raffel2020c4\", \"title\": \"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "83f1fcb5-fee7-42bc-9c5d-3efa2aa480a3",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "9e2e71bb-e6a0-489f-8d7d-0da76e04e91a",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 39, \\\"total_citations\\\": 76, \\\"unique_cited_keys\\\": 39, \\\"orphan_bib\\\": 0, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 35, \\\"online_not_found\\\": 0, \\\"online_mismatch\\\": 4}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 0, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"fang2024maskllm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\\\", \\\"authors\\\": \\\"Gongfan Fang and Hongxu Yin and Saurav Muralidharan and Greg Heinrich and Jeff P...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems (NeurIPS)\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\\\", \\\"authors\\\": \\\"Haotian Xu and Jiannan Yang and Tian Gao and Tsui-Wei Weng and Tengfei Ma\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning (ICML)\\\"}, {\\\"key\\\": \\\"muralidharan2024minitron\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Compact Language Models via Pruning and Knowledge Distillation\\\", \\\"authors\\\": \\\"Saurav Muralidharan and Sharath Turuvekere Sreenivas and Raviraj Joshi and Marci...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems (NeurIPS)\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\\\", \\\"authors\\\": \\\"Aayush Gautam and Mukul Gagrani and Junyoung Park and Mingu Lee and Chiris Lott ...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2602.00397\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Training-Free Activation Sparsity in Large Language Models\\\", \\\"authors\\\": \\\"James Liu and Pragaash Ponnusamy and Tianle Cai and Han Guo and Yoon Kim and Ben...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\\\", \\\"authors\\\": \\\"Zichang Liu and Jue Wang and Tri Dao and Tianyi Zhou and Binhang Yuan and Zhao S...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning (ICML)\\\"}, {\\\"key\\\": \\\"akhauri2024shadowllm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\\\", \\\"authors\\\": \\\"Yash Akhauri and Ahmed F AbouElhamayed and Jordan Dotzel and Zhiru Zhang and Ale...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\\\"}, {\\\"key\\\": \\\"lee2024cats\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\\\", \\\"authors\\\": \\\"Donghyun Lee and Je-Yong Lee and Genghan Zhang and Mo Tiwari and Azalia Mirhosei...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2404.08763\\\"}, {\\\"key\\\": \\\"zhang2025rsparse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\\\", \\\"authors\\\": \\\"Zhenyu Zhang and Zechun Liu and Yuandong Tian and Harshit Khaitan and Zhangyang ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"federici2025dip\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\\\", \\\"authors\\\": \\\"Marco Federici and Davide Belli and Mart van Baalen and Amir Jalalirad and Andri...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of Machine Learning and Systems (MLSys)\\\"}, {\\\"key\\\": \\\"shin2025sparseinfer\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\\\", \\\"authors\\\": \\\"Jiho Shin and Hoeseok Yang and Youngmin Yi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Design, Automation \\\\\\\\& Test in Europe Conference (DATE)\\\"}, {\\\"key\\\": \\\"serbin2026svdcsp\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"SVD Contextual Sparsity Predictors for Fast LLM Inference\\\", \\\"authors\\\": \\\"Georgii Serbin and Kirill Koshkin and Zhongao Sun and Anastasiya Bistrigova and ...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2603.14110\\\"}, {\\\"key\\\": \\\"mirzadeh2024relu\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\\\", \\\"authors\\\": \\\"Iman Mirzadeh and Keivan Alizadeh and Sachin Mehta and Carlo C Del Mundo and Onc...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"song2024turbosparse\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\\\", \\\"authors\\\": \\\"Yixin Song and Haotong Xie and Zhengyan Zhang and Bo Wen and Li Ma and Zeyu Mi a...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2406.05955\\\"}, {\\\"key\\\": \\\"song2025prosparse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\\\", \\\"authors\\\": \\\"Chenyang Song and Xu Han and Zhengyan Zhang and Shengding Hu and Xiyu Shi and Ku...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Computational Linguistics (COLING...\\\"}, {\\\"key\\\": \\\"luo2024sparsinglaw\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\\\", \\\"authors\\\": \\\"Yuqi Luo and Chenyang Song and Xu Han and Yingfa Chen and Chaojun Xiao and Xiaoj...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2411.02335\\\"}, {\\\"key\\\": \\\"song2024powerinfer\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\\\", \\\"authors\\\": \\\"Yixin Song and Zeyu Mi and Haotong Xie and Haibo Chen\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the ACM Symposium on Operating Systems Principles (SOSP)\\\"}, {\\\"key\\\": \\\"kim2016sequencekd\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Sequence-Level Knowledge Distillation\\\", \\\"authors\\\": \\\"Yoon Kim and Alexander M. Rush\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\\\"}, {\\\"key\\\": \\\"gu2024minillm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"MiniLLM: Knowledge Distillation of Large Language Models\\\", \\\"authors\\\": \\\"Yuxian Gu and Li Dong and Furu Wei and Minlie Huang\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"agarwal2024gkd\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\\\", \\\"authors\\\": \\\"Rishabh Agarwal and Nino Vieillard and Yongchao Zhou and Piotr Stanczyk and Sabe...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"khaki2025sparselora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\\\", \\\"authors\\\": \\\"Samir Khaki and Xiuyu Li and Junxian Guo and Ligeng Zhu and Konstantinos N. Plat...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning (ICML)\\\"}, {\\\"key\\\": \\\"raposo2024mod\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\\\", \\\"authors\\\": \\\"David Raposo and Sam Ritter and Blake Richards and Timothy Lillicrap and Peter C...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2404.02258\\\"}, {\\\"key\\\": \\\"sanh2019distilbert\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\\\", \\\"authors\\\": \\\"Victor Sanh and Lysandre Debut and Julien Chaumond and Thomas Wolf\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1910.01108\\\"}, {\\\"key\\\": \\\"sun2024wanda\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple and Effective Pruning Approach for Large Language Models\\\", \\\"authors\\\": \\\"Mingjie Sun and Zhuang Liu and Anna Bair and J. Zico Kolter\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"frantar2023sparsegpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\\\", \\\"authors\\\": \\\"Elias Frantar and Dan Alistarh\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning (ICML)\\\"}, {\\\"key\\\": \\\"szatkowski2024d2dmoe\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Exploiting Activation Sparsity with Dense to Dynamic-$k$ Mixture-of-Experts Conversion\\\", \\\"authors\\\": \\\"Filip Szatkowski and Bartosz W\\\\\\\\'ojcik and Miko\\\\\\\\laj Pi\\\\\\\\'orczy\\\\\\\\'nski and Simone Sc...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems (NeurIPS)\\\"}, {\\\"key\\\": \\\"fedus2022switch\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\\\", \\\"authors\\\": \\\"William Fedus and Barret Zoph and Noam Shazeer\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Journal of Machine Learning Research\\\"}, {\\\"key\\\": \\\"louizos2018l0\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Learning Sparse Neural Networks through $L_0$ Regularization\\\", \\\"authors\\\": \\\"Christos Louizos and Max Welling and Diederik P. Kingma\\\", \\\"year\\\": \\\"2018\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"maddison2017concrete\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\\\", \\\"authors\\\": \\\"Chris J. Maddison and Andriy Mnih and Yee Whye Teh\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"grattafiori2024llama3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Aaron Grattafiori and Abhimanyu Dubey and Abhinav Jauhri and Abhinav Pandey and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2407.21783\\\"}, {\\\"key\\\": \\\"qwen2024qwen25\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Qwen2.5 Technical Report\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2412.15115\\\"}, {\\\"key\\\": \\\"jiang2023mistral\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"authors\\\": \\\"Albert Q. Jiang and Alexandre Sablayrolles and Arthur Mensch and Chris Bamford a...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2310.06825\\\"}, {\\\"key\\\": \\\"jang2017gumbel\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Categorical Reparameterization with Gumbel-Softmax\\\", \\\"authors\\\": \\\"Eric Jang and Shixiang Gu and Ben Poole\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"shazeer2020glu\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"GLU Variants Improve Transformer\\\", \\\"authors\\\": \\\"Noam Shazeer\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2002.05202\\\"}, {\\\"key\\\": \\\"merity2017pointer\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Pointer Sentinel Mixture Models\\\", \\\"authors\\\": \\\"Stephen Merity and Caiming Xiong and James Bradbury and Richard Socher\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"hinton2015distilling\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Distilling the Knowledge in a Neural Network\\\", \\\"authors\\\": \\\"Geoffrey Hinton and Oriol Vinyals and Jeff Dean\\\", \\\"year\\\": \\\"2015\\\", \\\"venue\\\": \\\"NeurIPS 2014 Deep Learning Workshop\\\"}, {\\\"key\\\": \\\"bengio2013ste\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\\\", \\\"authors\\\": \\\"Yoshua Bengio and Nicholas L\\\\\\\\'eonard and Aaron Courville\\\", \\\"year\\\": \\\"2013\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1308.3432\\\"}, {\\\"key\\\": \\\"loshchilov2019adamw\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Decoupled Weight Decay Regularization\\\", \\\"authors\\\": \\\"Ilya Loshchilov and Frank Hutter\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations (ICLR)\\\"}, {\\\"key\\\": \\\"raffel2020c4\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\\\", \\\"authors\\\": \\\"Colin Raffel and Noam Shazeer and Adam Roberts and Katherine Lee and Sharan Nara...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Journal of Machine Learning Research\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"shazeer2020glu\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 3, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"jang2017gumbel\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grattafiori2024llama3\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"jiang2023mistral\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 20, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen2024qwen25\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 20, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lee2024cats\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"zhang2025rsparse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"federici2025dip\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shin2025sparseinfer\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"akhauri2024shadowllm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"serbin2026svdcsp\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"song2024powerinfer\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fang2024maskllm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 21, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mirzadeh2024relu\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"song2024turbosparse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"song2025prosparse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"luo2024sparsinglaw\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"muralidharan2024minitron\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 27, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sun2024wanda\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frantar2023sparsegpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fedus2022switch\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"raposo2024mod\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kim2016sequencekd\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sanh2019distilbert\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gu2024minillm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"agarwal2024gkd\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"khaki2025sparselora\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"maddison2017concrete\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 33, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"louizos2018l0\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 33, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shazeer2020glu\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"jang2017gumbel\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 49, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bengio2013ste\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 62, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"hinton2015distilling\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 80, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 175, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 176, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 176, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"akhauri2024shadowllm\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 176, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"szatkowski2024d2dmoe\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 176, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 183, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 184, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 184, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"szatkowski2024d2dmoe\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 185, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grattafiori2024llama3\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shazeer2020glu\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"loshchilov2019adamw\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"jang2017gumbel\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"merity2017pointer\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bengio2013ste\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 99, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gu2024minillm\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 103, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 106, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 113, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"jiang2023mistral\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 204, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen2024qwen25\\\", \\\"file\\\": \\\"experiments.tex\\\", \\\"line\\\": 227, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grattafiori2024llama3\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 19, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"jiang2023mistral\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 19, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"merity2017pointer\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 19, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"raffel2020c4\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 19, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 19, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 19, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"loshchilov2019adamw\\\", \\\"file\\\": \\\"ethics.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"raffel2020c4\\\", \\\"file\\\": \\\"appendix.tex\\\", \\\"line\\\": 154, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"file\\\": \\\"appendix.tex\\\", \\\"line\\\": 235, \\\"command\\\": \\\"cite\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"fang2024maskllm\\\", \\\"title\\\": \\\"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"xu2026spon\\\", \\\"title\\\": \\\"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"muralidharan2024minitron\\\", \\\"title\\\": \\\"Compact Language Models via Pruning and Knowledge Distillation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Compact Language Models via Pruning and Knowledge Distillation\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gautam2026fastforward\\\", \\\"title\\\": \\\"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"liu2025teal\\\", \\\"title\\\": \\\"Training-Free Activation Sparsity in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Training-Free Activation Sparsity in Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"liu2023dejavu\\\", \\\"title\\\": \\\"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"akhauri2024shadowllm\\\", \\\"title\\\": \\\"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"lee2024cats\\\", \\\"title\\\": \\\"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"zhang2025rsparse\\\", \\\"title\\\": \\\"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"federici2025dip\\\", \\\"title\\\": \\\"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.893, \\\"matched_title\\\": \\\"Code Artifact for Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shin2025sparseinfer\\\", \\\"title\\\": \\\"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"serbin2026svdcsp\\\", \\\"title\\\": \\\"SVD Contextual Sparsity Predictors for Fast LLM Inference\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SVD Contextual Sparsity Predictors for Fast LLM Inference\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mirzadeh2024relu\\\", \\\"title\\\": \\\"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"song2024turbosparse\\\", \\\"title\\\": \\\"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"song2025prosparse\\\", \\\"title\\\": \\\"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"luo2024sparsinglaw\\\", \\\"title\\\": \\\"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"song2024powerinfer\\\", \\\"title\\\": \\\"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"kim2016sequencekd\\\", \\\"title\\\": \\\"Sequence-Level Knowledge Distillation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Sequence-Level Knowledge Distillation\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gu2024minillm\\\", \\\"title\\\": \\\"MiniLLM: Knowledge Distillation of Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.893, \\\"matched_title\\\": \\\"MiniLLM: On-Policy Distillation of Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"agarwal2024gkd\\\", \\\"title\\\": \\\"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"khaki2025sparselora\\\", \\\"title\\\": \\\"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=khaki vs api=samir\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"raposo2024mod\\\", \\\"title\\\": \\\"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sanh2019distilbert\\\", \\\"title\\\": \\\"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sun2024wanda\\\", \\\"title\\\": \\\"A Simple and Effective Pruning Approach for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple and Effective Pruning Approach for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frantar2023sparsegpt\\\", \\\"title\\\": \\\"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"szatkowski2024d2dmoe\\\", \\\"title\\\": \\\"Exploiting Activation Sparsity with Dense to Dynamic-$k$ Mixture-of-Experts Conversion\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.988, \\\"matched_title\\\": \\\"Exploiting Activation Sparsity with Dense to Dynamic-k Mixture-of-Experts Conversion\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fedus2022switch\\\", \\\"title\\\": \\\"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"louizos2018l0\\\", \\\"title\\\": \\\"Learning Sparse Neural Networks through $L_0$ Regularization\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Learning Sparse Neural Networks through $L_0$ Regularization\\\", \\\"matched_year\\\": \\\"2017\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"maddison2017concrete\\\", \\\"title\\\": \\\"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"grattafiori2024llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen2024qwen25\\\", \\\"title\\\": \\\"Qwen2.5 Technical Report\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Qwen2.5 Technical Report\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=team vs api=qwen\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"jiang2023mistral\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mistral 7B\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"jang2017gumbel\\\", \\\"title\\\": \\\"Categorical Reparameterization with Gumbel-Softmax\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Categorical Reparameterization with Gumbel-Softmax\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shazeer2020glu\\\", \\\"title\\\": \\\"GLU Variants Improve Transformer\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLU Variants Improve Transformer\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"merity2017pointer\\\", \\\"title\\\": \\\"Pointer Sentinel Mixture Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Pointer Sentinel Mixture Models\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"hinton2015distilling\\\", \\\"title\\\": \\\"Distilling the Knowledge in a Neural Network\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Distilling the Knowledge in a Neural Network\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bengio2013ste\\\", \\\"title\\\": \\\"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\\\", \\\"matched_year\\\": \\\"2013\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"loshchilov2019adamw\\\", \\\"title\\\": \\\"Decoupled Weight Decay Regularization\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Decoupled Weight Decay Regularization\\\", \\\"matched_year\\\": \\\"2017\\\", \\\"mismatch_fields\\\": [\\\"year: bib=2019 vs api=2017\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"raffel2020c4\\\", \\\"title\\\": \\\"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 39, \"total_citations\": 76, \"unique_cited_keys\": 39, \"orphan_bib\": 0, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 35, \"online_not_found\": 0, \"online_mismatch\": 4}, \"cross_check\": {\"orphan_bib\": [], \"missing_bib\": [], \"orphan_count\": 0, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"fang2024maskllm\", \"type\": \"inproceedings\", \"title\": \"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\", \"authors\": \"Gongfan Fang and Hongxu Yin and Saurav Muralidharan and Greg Heinrich and Jeff P...\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems (NeurIPS)\"}, {\"key\": \"xu2026spon\", \"type\": \"inproceedings\", \"title\": \"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\", \"authors\": \"Haotian Xu and Jiannan Yang and Tian Gao and Tsui-Wei Weng and Tengfei Ma\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"muralidharan2024minitron\", \"type\": \"inproceedings\", \"title\": \"Compact Language Models via Pruning and Knowledge Distillation\", \"authors\": \"Saurav Muralidharan and Sharath Turuvekere Sreenivas and Raviraj Joshi and Marci...\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems (NeurIPS)\"}, {\"key\": \"gautam2026fastforward\", \"type\": \"article\", \"title\": \"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\", \"authors\": \"Aayush Gautam and Mukul Gagrani and Junyoung Park and Mingu Lee and Chiris Lott ...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2602.00397\"}, {\"key\": \"liu2025teal\", \"type\": \"inproceedings\", \"title\": \"Training-Free Activation Sparsity in Large Language Models\", \"authors\": \"James Liu and Pragaash Ponnusamy and Tianle Cai and Han Guo and Yoon Kim and Ben...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"liu2023dejavu\", \"type\": \"inproceedings\", \"title\": \"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\", \"authors\": \"Zichang Liu and Jue Wang and Tri Dao and Tianyi Zhou and Binhang Yuan and Zhao S...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"akhauri2024shadowllm\", \"type\": \"inproceedings\", \"title\": \"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\", \"authors\": \"Yash Akhauri and Ahmed F AbouElhamayed and Jordan Dotzel and Zhiru Zhang and Ale...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"lee2024cats\", \"type\": \"article\", \"title\": \"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\", \"authors\": \"Donghyun Lee and Je-Yong Lee and Genghan Zhang and Mo Tiwari and Azalia Mirhosei...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2404.08763\"}, {\"key\": \"zhang2025rsparse\", \"type\": \"inproceedings\", \"title\": \"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\", \"authors\": \"Zhenyu Zhang and Zechun Liu and Yuandong Tian and Harshit Khaitan and Zhangyang ...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"federici2025dip\", \"type\": \"inproceedings\", \"title\": \"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\", \"authors\": \"Marco Federici and Davide Belli and Mart van Baalen and Amir Jalalirad and Andri...\", \"year\": \"2024\", \"venue\": \"Proceedings of Machine Learning and Systems (MLSys)\"}, {\"key\": \"shin2025sparseinfer\", \"type\": \"inproceedings\", \"title\": \"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\", \"authors\": \"Jiho Shin and Hoeseok Yang and Youngmin Yi\", \"year\": \"2025\", \"venue\": \"Proceedings of the Design, Automation \\\\& Test in Europe Conference (DATE)\"}, {\"key\": \"serbin2026svdcsp\", \"type\": \"article\", \"title\": \"SVD Contextual Sparsity Predictors for Fast LLM Inference\", \"authors\": \"Georgii Serbin and Kirill Koshkin and Zhongao Sun and Anastasiya Bistrigova and ...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2603.14110\"}, {\"key\": \"mirzadeh2024relu\", \"type\": \"inproceedings\", \"title\": \"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\", \"authors\": \"Iman Mirzadeh and Keivan Alizadeh and Sachin Mehta and Carlo C Del Mundo and Onc...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"song2024turbosparse\", \"type\": \"article\", \"title\": \"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\", \"authors\": \"Yixin Song and Haotong Xie and Zhengyan Zhang and Bo Wen and Li Ma and Zeyu Mi a...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2406.05955\"}, {\"key\": \"song2025prosparse\", \"type\": \"inproceedings\", \"title\": \"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\", \"authors\": \"Chenyang Song and Xu Han and Zhengyan Zhang and Shengding Hu and Xiyu Shi and Ku...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Computational Linguistics (COLING...\"}, {\"key\": \"luo2024sparsinglaw\", \"type\": \"article\", \"title\": \"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\", \"authors\": \"Yuqi Luo and Chenyang Song and Xu Han and Yingfa Chen and Chaojun Xiao and Xiaoj...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2411.02335\"}, {\"key\": \"song2024powerinfer\", \"type\": \"inproceedings\", \"title\": \"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\", \"authors\": \"Yixin Song and Zeyu Mi and Haotong Xie and Haibo Chen\", \"year\": \"2024\", \"venue\": \"Proceedings of the ACM Symposium on Operating Systems Principles (SOSP)\"}, {\"key\": \"kim2016sequencekd\", \"type\": \"inproceedings\", \"title\": \"Sequence-Level Knowledge Distillation\", \"authors\": \"Yoon Kim and Alexander M. Rush\", \"year\": \"2016\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"gu2024minillm\", \"type\": \"inproceedings\", \"title\": \"MiniLLM: Knowledge Distillation of Large Language Models\", \"authors\": \"Yuxian Gu and Li Dong and Furu Wei and Minlie Huang\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"agarwal2024gkd\", \"type\": \"inproceedings\", \"title\": \"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\", \"authors\": \"Rishabh Agarwal and Nino Vieillard and Yongchao Zhou and Piotr Stanczyk and Sabe...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"khaki2025sparselora\", \"type\": \"inproceedings\", \"title\": \"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\", \"authors\": \"Samir Khaki and Xiuyu Li and Junxian Guo and Ligeng Zhu and Konstantinos N. Plat...\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"raposo2024mod\", \"type\": \"article\", \"title\": \"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\", \"authors\": \"David Raposo and Sam Ritter and Blake Richards and Timothy Lillicrap and Peter C...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2404.02258\"}, {\"key\": \"sanh2019distilbert\", \"type\": \"article\", \"title\": \"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\", \"authors\": \"Victor Sanh and Lysandre Debut and Julien Chaumond and Thomas Wolf\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1910.01108\"}, {\"key\": \"sun2024wanda\", \"type\": \"inproceedings\", \"title\": \"A Simple and Effective Pruning Approach for Large Language Models\", \"authors\": \"Mingjie Sun and Zhuang Liu and Anna Bair and J. Zico Kolter\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"frantar2023sparsegpt\", \"type\": \"inproceedings\", \"title\": \"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\", \"authors\": \"Elias Frantar and Dan Alistarh\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning (ICML)\"}, {\"key\": \"szatkowski2024d2dmoe\", \"type\": \"inproceedings\", \"title\": \"Exploiting Activation Sparsity with Dense to Dynamic-$k$ Mixture-of-Experts Conversion\", \"authors\": \"Filip Szatkowski and Bartosz W\\\\'ojcik and Miko\\\\laj Pi\\\\'orczy\\\\'nski and Simone Sc...\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems (NeurIPS)\"}, {\"key\": \"fedus2022switch\", \"type\": \"article\", \"title\": \"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\", \"authors\": \"William Fedus and Barret Zoph and Noam Shazeer\", \"year\": \"2022\", \"venue\": \"Journal of Machine Learning Research\"}, {\"key\": \"louizos2018l0\", \"type\": \"inproceedings\", \"title\": \"Learning Sparse Neural Networks through $L_0$ Regularization\", \"authors\": \"Christos Louizos and Max Welling and Diederik P. Kingma\", \"year\": \"2018\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"maddison2017concrete\", \"type\": \"inproceedings\", \"title\": \"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\", \"authors\": \"Chris J. Maddison and Andriy Mnih and Yee Whye Teh\", \"year\": \"2017\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"grattafiori2024llama3\", \"type\": \"article\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Aaron Grattafiori and Abhimanyu Dubey and Abhinav Jauhri and Abhinav Pandey and ...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2407.21783\"}, {\"key\": \"qwen2024qwen25\", \"type\": \"article\", \"title\": \"Qwen2.5 Technical Report\", \"authors\": \"Qwen Team\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2412.15115\"}, {\"key\": \"jiang2023mistral\", \"type\": \"article\", \"title\": \"Mistral 7B\", \"authors\": \"Albert Q. Jiang and Alexandre Sablayrolles and Arthur Mensch and Chris Bamford a...\", \"year\": \"2023\", \"venue\": \"arXiv preprint arXiv:2310.06825\"}, {\"key\": \"jang2017gumbel\", \"type\": \"inproceedings\", \"title\": \"Categorical Reparameterization with Gumbel-Softmax\", \"authors\": \"Eric Jang and Shixiang Gu and Ben Poole\", \"year\": \"2017\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"shazeer2020glu\", \"type\": \"article\", \"title\": \"GLU Variants Improve Transformer\", \"authors\": \"Noam Shazeer\", \"year\": \"2020\", \"venue\": \"arXiv preprint arXiv:2002.05202\"}, {\"key\": \"merity2017pointer\", \"type\": \"inproceedings\", \"title\": \"Pointer Sentinel Mixture Models\", \"authors\": \"Stephen Merity and Caiming Xiong and James Bradbury and Richard Socher\", \"year\": \"2017\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"hinton2015distilling\", \"type\": \"inproceedings\", \"title\": \"Distilling the Knowledge in a Neural Network\", \"authors\": \"Geoffrey Hinton and Oriol Vinyals and Jeff Dean\", \"year\": \"2015\", \"venue\": \"NeurIPS 2014 Deep Learning Workshop\"}, {\"key\": \"bengio2013ste\", \"type\": \"article\", \"title\": \"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\", \"authors\": \"Yoshua Bengio and Nicholas L\\\\'eonard and Aaron Courville\", \"year\": \"2013\", \"venue\": \"arXiv preprint arXiv:1308.3432\"}, {\"key\": \"loshchilov2019adamw\", \"type\": \"inproceedings\", \"title\": \"Decoupled Weight Decay Regularization\", \"authors\": \"Ilya Loshchilov and Frank Hutter\", \"year\": \"2019\", \"venue\": \"Proceedings of the International Conference on Learning Representations (ICLR)\"}, {\"key\": \"raffel2020c4\", \"type\": \"article\", \"title\": \"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\", \"authors\": \"Colin Raffel and Noam Shazeer and Adam Roberts and Katherine Lee and Sharan Nara...\", \"year\": \"2020\", \"venue\": \"Journal of Machine Learning Research\"}], \"tex_citations\": [{\"key\": \"shazeer2020glu\", \"file\": \"introduction.tex\", \"line\": 3, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"introduction.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"introduction.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"jang2017gumbel\", \"file\": \"introduction.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"grattafiori2024llama3\", \"file\": \"introduction.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"jiang2023mistral\", \"file\": \"introduction.tex\", \"line\": 20, \"command\": \"cite\"}, {\"key\": \"qwen2024qwen25\", \"file\": \"introduction.tex\", \"line\": 20, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"related_work.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"lee2024cats\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"zhang2025rsparse\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"federici2025dip\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"shin2025sparseinfer\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"akhauri2024shadowllm\", \"file\": \"related_work.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"related_work.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"serbin2026svdcsp\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"song2024powerinfer\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"fang2024maskllm\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"related_work.tex\", \"line\": 21, \"command\": \"cite\"}, {\"key\": \"mirzadeh2024relu\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"song2024turbosparse\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"song2025prosparse\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"luo2024sparsinglaw\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"muralidharan2024minitron\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"sun2024wanda\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"frantar2023sparsegpt\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"fedus2022switch\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"raposo2024mod\", \"file\": \"related_work.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"kim2016sequencekd\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"sanh2019distilbert\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"gu2024minillm\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"agarwal2024gkd\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"khaki2025sparselora\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"maddison2017concrete\", \"file\": \"related_work.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"louizos2018l0\", \"file\": \"related_work.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"shazeer2020glu\", \"file\": \"method.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"method.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"jang2017gumbel\", \"file\": \"method.tex\", \"line\": 49, \"command\": \"cite\"}, {\"key\": \"bengio2013ste\", \"file\": \"method.tex\", \"line\": 62, \"command\": \"cite\"}, {\"key\": \"hinton2015distilling\", \"file\": \"method.tex\", \"line\": 80, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"method.tex\", \"line\": 175, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"akhauri2024shadowllm\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"szatkowski2024d2dmoe\", \"file\": \"method.tex\", \"line\": 176, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"method.tex\", \"line\": 183, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"method.tex\", \"line\": 184, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"method.tex\", \"line\": 184, \"command\": \"cite\"}, {\"key\": \"szatkowski2024d2dmoe\", \"file\": \"method.tex\", \"line\": 185, \"command\": \"cite\"}, {\"key\": \"grattafiori2024llama3\", \"file\": \"experiments.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"shazeer2020glu\", \"file\": \"experiments.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"loshchilov2019adamw\", \"file\": \"experiments.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"jang2017gumbel\", \"file\": \"experiments.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"merity2017pointer\", \"file\": \"experiments.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"experiments.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"experiments.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"experiments.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"experiments.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"liu2023dejavu\", \"file\": \"experiments.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"experiments.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"bengio2013ste\", \"file\": \"experiments.tex\", \"line\": 99, \"command\": \"cite\"}, {\"key\": \"gu2024minillm\", \"file\": \"experiments.tex\", \"line\": 103, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"experiments.tex\", \"line\": 106, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"experiments.tex\", \"line\": 113, \"command\": \"cite\"}, {\"key\": \"jiang2023mistral\", \"file\": \"experiments.tex\", \"line\": 204, \"command\": \"cite\"}, {\"key\": \"qwen2024qwen25\", \"file\": \"experiments.tex\", \"line\": 227, \"command\": \"cite\"}, {\"key\": \"grattafiori2024llama3\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"jiang2023mistral\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"merity2017pointer\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"raffel2020c4\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"liu2025teal\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"xu2026spon\", \"file\": \"ethics.tex\", \"line\": 19, \"command\": \"cite\"}, {\"key\": \"loshchilov2019adamw\", \"file\": \"ethics.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"raffel2020c4\", \"file\": \"appendix.tex\", \"line\": 154, \"command\": \"cite\"}, {\"key\": \"gautam2026fastforward\", \"file\": \"appendix.tex\", \"line\": 235, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"fang2024maskllm\", \"title\": \"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MaskLLM: Learnable Semi-Structured Sparsity for Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"xu2026spon\", \"title\": \"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"muralidharan2024minitron\", \"title\": \"Compact Language Models via Pruning and Knowledge Distillation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Compact Language Models via Pruning and Knowledge Distillation\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gautam2026fastforward\", \"title\": \"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"liu2025teal\", \"title\": \"Training-Free Activation Sparsity in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Training-Free Activation Sparsity in Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"liu2023dejavu\", \"title\": \"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"akhauri2024shadowllm\", \"title\": \"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"lee2024cats\", \"title\": \"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"zhang2025rsparse\", \"title\": \"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"federici2025dip\", \"title\": \"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\", \"status\": \"verified\", \"confidence\": 0.893, \"matched_title\": \"Code Artifact for Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shin2025sparseinfer\", \"title\": \"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"serbin2026svdcsp\", \"title\": \"SVD Contextual Sparsity Predictors for Fast LLM Inference\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SVD Contextual Sparsity Predictors for Fast LLM Inference\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mirzadeh2024relu\", \"title\": \"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"song2024turbosparse\", \"title\": \"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"song2025prosparse\", \"title\": \"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"luo2024sparsinglaw\", \"title\": \"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"song2024powerinfer\", \"title\": \"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"PowerInfer: Fast Large Language Model Serving with a Consumer-grade GPU\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"kim2016sequencekd\", \"title\": \"Sequence-Level Knowledge Distillation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Sequence-Level Knowledge Distillation\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gu2024minillm\", \"title\": \"MiniLLM: Knowledge Distillation of Large Language Models\", \"status\": \"verified\", \"confidence\": 0.893, \"matched_title\": \"MiniLLM: On-Policy Distillation of Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"agarwal2024gkd\", \"title\": \"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On-Policy Distillation of Language Models: Learning from Self-Generated Mistakes\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"khaki2025sparselora\", \"title\": \"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"SparseLoRA: Accelerating LLM Fine-Tuning with Contextual Sparsity\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=khaki vs api=samir\"], \"note\": \"\"}, {\"key\": \"raposo2024mod\", \"title\": \"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mixture-of-Depths: Dynamically allocating compute in transformer-based language models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sanh2019distilbert\", \"title\": \"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DistilBERT, a distilled version of BERT: smaller, faster, cheaper and lighter\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sun2024wanda\", \"title\": \"A Simple and Effective Pruning Approach for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple and Effective Pruning Approach for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frantar2023sparsegpt\", \"title\": \"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SparseGPT: Massive Language Models Can Be Accurately Pruned in One-Shot\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"szatkowski2024d2dmoe\", \"title\": \"Exploiting Activation Sparsity with Dense to Dynamic-$k$ Mixture-of-Experts Conversion\", \"status\": \"verified\", \"confidence\": 0.988, \"matched_title\": \"Exploiting Activation Sparsity with Dense to Dynamic-k Mixture-of-Experts Conversion\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fedus2022switch\", \"title\": \"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"louizos2018l0\", \"title\": \"Learning Sparse Neural Networks through $L_0$ Regularization\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Learning Sparse Neural Networks through $L_0$ Regularization\", \"matched_year\": \"2017\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"maddison2017concrete\", \"title\": \"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Concrete Distribution: A Continuous Relaxation of Discrete Random Variables\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"grattafiori2024llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"qwen2024qwen25\", \"title\": \"Qwen2.5 Technical Report\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Qwen2.5 Technical Report\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=team vs api=qwen\"], \"note\": \"\"}, {\"key\": \"jiang2023mistral\", \"title\": \"Mistral 7B\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mistral 7B\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"jang2017gumbel\", \"title\": \"Categorical Reparameterization with Gumbel-Softmax\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Categorical Reparameterization with Gumbel-Softmax\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shazeer2020glu\", \"title\": \"GLU Variants Improve Transformer\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLU Variants Improve Transformer\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"merity2017pointer\", \"title\": \"Pointer Sentinel Mixture Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Pointer Sentinel Mixture Models\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"hinton2015distilling\", \"title\": \"Distilling the Knowledge in a Neural Network\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Distilling the Knowledge in a Neural Network\", \"matched_year\": \"2015\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bengio2013ste\", \"title\": \"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Estimating or Propagating Gradients Through Stochastic Neurons for Conditional Computation\", \"matched_year\": \"2013\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"loshchilov2019adamw\", \"title\": \"Decoupled Weight Decay Regularization\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Decoupled Weight Decay Regularization\", \"matched_year\": \"2017\", \"mismatch_fields\": [\"year: bib=2019 vs api=2017\"], \"note\": \"\"}, {\"key\": \"raffel2020c4\", \"title\": \"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Exploring the Limits of Transfer Learning with a Unified Text-to-Text Transformer\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "83f1fcb5-fee7-42bc-9c5d-3efa2aa480a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 53_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。  ## Venue 信息 - **目标**: EMNLP 2026 (ARR May 2026 cycle) - **截止日期**: 2026-05-25 - **格式**: ACL style, Long paper ≤8 页正文, double-blind - **评分标准*…",
  "leafUuid": "9e2e71bb-e6a0-489f-8d7d-0da76e04e91a",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Runtime record

_source line 54_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Tool result

_source line 55 · 2026-05-18T12:25:54.235Z_

<details><summary>↩ Tool result · `toolu_01KhnaVvDKVP18cpibLALQ3U`</summary>

```text
# ARR Reviewer Guidelines: Key Evaluation Principles

## What Reviewers Should Evaluate

Reviewers assess papers across multiple dimensions. The core evaluation focuses on **technical soundness, novelty, clarity, and contribution to the field**. Papers must be "sufficiently sound and reproducible" for acceptance at main venues.

Key assessment areas include:
- Research question clarity and appropriateness
- Methodological validity and completeness
- Evidence quality supporting claims
- Novelty relative to prior work
- Reproducibility and implementation details

## Scoring: Soundness and Excitement

ARR uses three scores (as of February 2025):

**Soundness**: "must be justified by the text of the review." Low soundness scores require explicit explanation of technical flaws. Reviewers should identify specific methodological problems, incomplete proofs, or invalid assumptions.

**Excitement**: Orthogonal to soundness, reflecting "personal taste" about topic interest. A paper can be technically sound but personally unexciting, or vice versa.

**Overall Assessment**: A composite recommendation balancing soundness, excitement, novelty, and potential impact—not solely dependent on any single factor.

## Strengths vs. Weaknesses: Critical Distinctions

The guidelines identify **common review mistakes** that mischaracterize papers:

| Problematic | Why It's Flawed |
|---|---|
| "Results seem obvious" | Findings often appear intuitive retrospectively but lack prior empirical validation |
| "Method too simple" | Simplicity is preferable; complexity doesn't equal quality |
| "No SOTA results" | SOTA isn't necessary for scientific contribution |
| "Negative results" | Publishing negatives combats publication bias |
| "Paper lacks experiment X" | Only required if X is essential to the core claim |

**Legitimate weaknesses** include: incomplete assumptions, invalid proofs, unfair baseline comparisons, undisclosed data quality issues, or claims unsupported by presented evidence.

## Experimental Rigor Guidance

Key expectations:

- **Reproducibility**: "Enough details to reproduce experiments, including hyperparameter selection" and code availability status
- **Statistical significance**: "Error bars, confidence intervals, statistical significance tests"
- **Fair comparisons**: Baselines must be "well-tuned"; avoid "p-hacking" or cherry-picking results
- **Appropriate scope**: Claims must match evaluated samples; "few QA benchmarks ≠ 'reasoning'"
- **Analysis quality**: Avoid "misleading statistics or data presentation"

## Claims vs. Evidence Standards

The guidelines emphasize: **Every claim requires evidence or clear argumentation—or explicit marking as speculation.**

Problematic patterns include:
- "Hypotheses/speculations presented as conclusions"
- Overclaiming (e.g., concluding LLMs "understand" language from benchmark scores)
- Relying on "bad precedents" without justification

Authors must clearly distinguish established findings from exploratory observations.

## Additional Critical Requirements

- **Confidentiality**: Never upload submissions/reviews to non-privacy-preserving AI tools
- **Anonymity protocol**: Read papers fully before searching related work; disclose if author identity becomes known
- **Professional tone**: "Write the review you would like to get yourself"
- **Author engagement**: Acknowledge responses; update scores if concerns are addressed

The guidelines emphasize that peer review should balance rigor with intellectual generosity, recognizing that "simpler solutions are preferable" and that "interdisciplinary contributions" deserve fair evaluation.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1a3eacba-d3e9-44ff-a597-eebc19989942",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "3b630fdc-95bc-447b-983e-556279c65c0b",
  "toolUseResult": {
    "bytes": 100603,
    "code": 200,
    "codeText": "OK",
    "result": "# ARR Reviewer Guidelines: Key Evaluation Principles\n\n## What Reviewers Should Evaluate\n\nReviewers assess papers across multiple dimensions. The core evaluation focuses on **technical soundness, novelty, clarity, and contribution to the field**. Papers must be \"sufficiently sound and reproducible\" for acceptance at main venues.\n\nKey assessment areas include:\n- Research question clarity and appropriateness\n- Methodological validity and completeness\n- Evidence quality supporting claims\n- Novelty relative to prior work\n- Reproducibility and implementation details\n\n## Scoring: Soundness and Excitement\n\nARR uses three scores (as of February 2025):\n\n**Soundness**: \"must be justified by the text of the review.\" Low soundness scores require explicit explanation of technical flaws. Reviewers should identify specific methodological problems, incomplete proofs, or invalid assumptions.\n\n**Excitement**: Orthogonal to soundness, reflecting \"personal taste\" about topic interest. A paper can be technically sound but personally unexciting, or vice versa.\n\n**Overall Assessment**: A composite recommendation balancing soundness, excitement, novelty, and potential impact—not solely dependent on any single factor.\n\n## Strengths vs. Weaknesses: Critical Distinctions\n\nThe guidelines identify **common review mistakes** that mischaracterize papers:\n\n| Problematic | Why It's Flawed |\n|---|---|\n| \"Results seem obvious\" | Findings often appear intuitive retrospectively but lack prior empirical validation |\n| \"Method too simple\" | Simplicity is preferable; complexity doesn't equal quality |\n| \"No SOTA results\" | SOTA isn't necessary for scientific contribution |\n| \"Negative results\" | Publishing negatives combats publication bias |\n| \"Paper lacks experiment X\" | Only required if X is essential to the core claim |\n\n**Legitimate weaknesses** include: incomplete assumptions, invalid proofs, unfair baseline comparisons, undisclosed data quality issues, or claims unsupported by presented evidence.\n\n## Experimental Rigor Guidance\n\nKey expectations:\n\n- **Reproducibility**: \"Enough details to reproduce experiments, including hyperparameter selection\" and code availability status\n- **Statistical significance**: \"Error bars, confidence intervals, statistical significance tests\"\n- **Fair comparisons**: Baselines must be \"well-tuned\"; avoid \"p-hacking\" or cherry-picking results\n- **Appropriate scope**: Claims must match evaluated samples; \"few QA benchmarks ≠ 'reasoning'\"\n- **Analysis quality**: Avoid \"misleading statistics or data presentation\"\n\n## Claims vs. Evidence Standards\n\nThe guidelines emphasize: **Every claim requires evidence or clear argumentation—or explicit marking as speculation.**\n\nProblematic patterns include:\n- \"Hypotheses/speculations presented as conclusions\"\n- Overclaiming (e.g., concluding LLMs \"understand\" language from benchmark scores)\n- Relying on \"bad precedents\" without justification\n\nAuthors must clearly distinguish established findings from exploratory observations.\n\n## Additional Critical Requirements\n\n- **Confidentiality**: Never upload submissions/reviews to non-privacy-preserving AI tools\n- **Anonymity protocol**: Read papers fully before searching related work; disclose if author identity becomes known\n- **Professional tone**: \"Write the review you would like to get yourself\"\n- **Author engagement**: Acknowledge responses; update scores if concerns are addressed\n\nThe guidelines emphasize that peer review should balance rigor with intellectual generosity, recognizing that \"simpler solutions are preferable\" and that \"interdisciplinary contributions\" deserve fair evaluation.",
    "durationMs": 11647,
    "url": "https://aclrollingreview.org/reviewerguidelines"
  },
  "sourceToolAssistantUUID": "1a3eacba-d3e9-44ff-a597-eebc19989942",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 56 · 2026-05-18T12:28:24.570Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information I need. Let me compile a thorough review.

Let me analyze the paper carefully:

## Paper Summary
The paper proposes replacing BCE loss with forward KL divergence for training activation sparsity predictors in SwiGLU LLMs. The core argument is that BCE trains each neuron independently while inference uses global top-k allocation (TEAL), creating a "structural mismatch." The KL objective couples all neurons through the output distribution. Results on LLaMA-3.1-8B show KL predictors achieve lower perplexity than TEAL at 30-70% sparsity, with cross-architecture validation on Mistral-7B and Qwen-2.5-14B.


## Method Analysis

### Gradient analysis (§3.5)
The paper derives the gradient structures for both objectives—BCE operates per-neuron while KL propagates through downstream layers via the Jacobian. The mathematical derivation is sound, but the "structural mismatch" framing oversimplifies what's really a fundamental property of end-to-end training: any objective that backpropagates through the full computation graph will couple gradients across neurons. The empirical question of whether this particular coupling improves performance is what matters, not the theoretical observation itself.

The paper does acknowledge this confound in §4.3, noting that disentangling gradient effects from the oracle quality difference remains unresolved. This honesty is valuable but also suggests the core narrative rests on an incomplete analysis.

### SNR Measurements
The measurements span only 7 checkpoints across 300 training steps rather than the full 1000-step run, with bootstrap confidence intervals reported but sample size unspecified. The non-monotonic pattern where BCE outperforms KL mid-training actually complicates the story rather than supporting it. There's also a methodological question: SNR is evaluated on C4 data while the model trains on WikiText-103, which seems like it could introduce confounds.

### Gumbel-Sigmoid (§3

.3)
Training uses soft continuous masks while inference switches to hard masks via TEAL top-k selection, with temperature annealing (1.0 → 0.1) bridging the gap implicitly. But there's no explicit quantification of this train-test mismatch—what actually happens if you use soft masks at inference? The appendix reveals per-token evaluation numbers that are substantially better than the hard TEAL evaluation (9.218 vs 11.963 for d_b=128), exposing a significant gap that the paper doesn't directly address.

### Adaptive Penalty Controller (§3.5)
At the 30% sparsity target, actual sparsity lands at 28.5%, a 5% deviation the paper treats as negligible.

The controller hits its maximum penalty at the boundary conditions of 30% and 70% sparsity, suggesting the adaptive mechanism actually fails to converge properly at these points. Interpolating TEAL to match the 28.5% actual sparsity would yield around 10.7 PPL versus 10.97 at 30%, making the comparison between KL and TEAL slightly unfair since they're being evaluated at different sparsity levels.

### BCE Comparison Fairness
There's a fundamental mismatch in how these methods are set up: KL uses Gumbel-Sigmoid relaxation with adaptive penalty control for sparsity, while BCE relies on hard masks with magnitude-based oracle thresholds. They're optimizing different objectives entirely—KL targets the output distribution while BCE optimizes per-neuron classification. The ablation adding Gumbel and penalty to BCE (Table 3, 38.02 PPL) performs much worse than vanilla BCE (27.97), which suggests the components don't transfer cleanly across methods.

### Statistical Power
The seed counts are inconsistent across experiments: KL gets 3 seeds at 30% but TEAL is deterministic with just one, while at 50% both have 3 seeds. Mistral and Qwen-14B results are all single-seed, and the 70% results lack replication entirely. For a paper claiming 18% PPL improvement, relying on single-seed Mistral runs is a significant weakness.

### OOD Evaluation
WikiText-103 to WikiText-2 isn't truly out-of-distribution since they're from the same corpus, just different splits. C4 evaluation exists but appears incomplete.

### Cross-Architecture
Mistral-7B only reports perplexity without downstream tasks, while Qwen-14B shows a concerning gap where KL's MMLU score (63.7%) substantially underperforms TEAL (71.8%). The paper's explanation about KL's output-preservation objective being the cause is speculative.

### Regime Analysis
With only three sparsity levels tested, claiming three distinct operating regions from three data points is underdetermined. The paper acknowledges this limitation but doesn't address it.

### Compensation Redundancy
At 50% sparsity, all five metrics match KL-only performance, and at 30% the standard deviations overlap, confirming redundancy—though this is only verified at two sparsity levels.

### Missing Comparisons
The paper positions itself within a taxonomy but lacks comparisons to several relevant baselines like ShadowLLM, D2DMoE, R-Sparse, and DIP.

## Strengths
The core contribution—identifying the BCE/global-top-k mismatch—addresses a genuine practical problem, and the paper backs this up with thorough ablations, honest acknowledgment of limitations, and useful positioning via the taxonomy. The writing is clear throughout.

## Weaknesses
The structural mismatch claim feels somewhat circular and well-established, the confounding between loss function and pipeline differences can't be cleanly separated, intermediate-coupling methods are absent from comparisons, and the train-test gap between soft and hard masks remains unquantified. Statistical power also falls short for some key findings.

The "three operating regions" conclusion rests on just three data points, the Qwen-14B MMLU gap is a concerning negative result that questions generality, and there's no wall-clock speedup measurement. On the structural mismatch specifically, the paper correctly identifies that BCE's per-neuron gradients don't align with global top-k inference, but this is really just saying that optimizing a mismatched proxy hurts performance—the deeper question of whether the issue stems from gradient coupling or KL's direct metric alignment remains unclear. The loss function isolation ablation muddies this further rather than clarifying it.

Looking at the Gumbel train-test gap more carefully, the per-token evaluation shows a substantial 22.9% gap between the predictor's soft mask performance and TEAL's hard top-k filtering, which is significant but goes unexamined in the paper. This gap likely reflects the difference between soft masks without global budget constraints versus the constrained hard selection, which matters for understanding where the actual performance loss comes from.

The 40% regime results are puzzling—the uniform allocation gives lower PPL at 40% sparsity than at 30%, which shouldn't happen if higher sparsity degrades performance. Let me reconsider what's actually being measured here. I'm noticing something strange here — the 40% sparsity model with uniform allocation achieves lower perplexity (8.36) than the 30% model (8.82), which shouldn't happen if removing more neurons degrades performance. This could point to a training or calibration difference between the two predictors, or possibly an inconsistency in how the evaluation was conducted.

Let me verify the experimental setup more carefully. Both use seed 42 for evaluation, so they should be directly comparable. The 40% model might have learned to identify truly important neurons more effectively, allowing it to maintain better performance despite higher sparsity — though that seems physically unlikely. I should check the experiment IDs to understand what's actually being compared here.

The caption claims each row uses a predictor trained at that sparsity level, but the 40% entry's ID suggests it might be trained at 30%, which would explain the anomaly. As a reviewer, I can flag this inconsistency without over-interpreting the naming convention. The counterintuitive PPL result (40% < 30%) is worth highlighting since it could indicate either a data issue or an important finding that wasn't discussed. Let me also consider whether the 30% target might have actual sparsity around 28.5% due to deviation, which could affect the comparison.

Actually, I think I've found the real explanation: the penalty controller saturates at its cap (5000) when targeting 30%, which suggests the optimization is struggling and the predictor quality suffers. At 40%, the controller converges to 625 without hitting the cap, indicating better optimization. This could genuinely explain why the 40% predictor achieves better PPL despite higher sparsity—it's a meaningful finding the paper doesn't acknowledge about the controller's limitations.

Now I should draft the review with focus on the substantive issues. Let me verify one more detail about the KL global results at 30% before finalizing my assessment.

Looking at the reported numbers more carefully, I'm seeing that 40% uniform actually outperforms 30% uniform in PPL (8.36 vs 8.82), which is counterintuitive and worth investigating. For Qwen-14B, the results show KL achieving better PPL but worse MMLU compared to TEAL and BCE, which suggests a trade-off in how these methods optimize different objectives. So KL achieves 13% better PPL but 11% worse MMLU. This is a significant negative result. The paper acknowledges it but doesn't have a good explanation. The suggestion that "KL's output-preservation objective may underweight task-specific features at higher knowledge densities" is speculative.

This is important because MMLU is arguably a more meaningful metric than PPL for practical applications. If KL-trained predictors systematically trade PPL for MMLU at larger scales, the practical value diminishes.

The conclusion is just one sentence about halving PPL and reducing cross-seed variance — unusually minimal for a conference paper. And looking at the training setup: WikiText-103 with only 1000 steps, batch size 4, and sequence length 2048 means they're training on about 8.19M tokens, which is roughly 8% of the full dataset. That's actually quite efficient.

Now I need to organize the review. The central issue is that the KL versus BCE comparison conflates multiple pipeline differences, so the claim that KL outperforms due to structural mismatch isn't properly isolated. - Loss function (KL vs BCE)
- Oracle source (output distribution vs magnitude-based)  
- Mask relaxation (Gumbel-Sigmoid continuous vs hard threshold for BCE)
- Sparsity control (adaptive penalty vs built-in via oracle threshold)

The "loss function isolation" ablation doesn't cleanly separate the loss function's effect because the penalty mechanism is tightly coupled to KL optimization and likely confounds the results. What's really needed is testing KL with magnitude-based oracles or BCE with KL-derived oracles to isolate the actual source of improvement. The paper mentions this limitation but still emphasizes "structural mismatch" as though the evidence clearly supports it, which is a meaningful disconnect between what's claimed and what's actually demonstrated.

The taxonomy positions three coupling levels—Decomposed (BCE), Intermediate (MSE), and Coupled (KL)—but the experiments only pit Decomposed against Coupled. ShadowLLM and D2DMoE both use intermediate MSE coupling and are cited as related work, yet they're never directly compared. If intermediate approaches already capture most of the gains, the case for full end-to-end KL becomes much weaker.

There's also a concerning pattern with the Qwen-14B results: KL improves perplexity but substantially hurts MMLU (63.7% vs 71.8% for TEAL/BCE). The abstract and introduction emphasize the PPL advantage across model sizes without adequately flagging that the more practically relevant metric actually degrades, creating a misleading framing of the results. with PPL improvements but MMLU is arguably more relevant for deployment. The explanation ("scale-dependent effects") is speculative without mechanistic support.

There's a concerning pattern in the experimental design. The three operating regions identified in Table 4 come from just three sparsity levels—that's fitting a three-parameter model to three data points, so the regime boundaries are essentially unconstrained. The paper acknowledges this but still presents it as a finding; denser sampling across more sparsity levels would be needed to actually validate where these boundaries lie.

I'm also noticing Table 4 shows 40% uniform PPL is actually lower than 30%, which shouldn't happen when removing more neurons. This anomaly isn't discussed at all, yet it could point to something important—either the penalty controller saturating at 30%, a measurement error, or something genuinely interesting about the sparsity landscape that deserves investigation.

There's also a substantial train-test mismatch that's buried in the appendix. The soft masks used during training give PPL 9.218, but the hard top-k masks at inference yield PPL 11.963—a 30% gap. Temperature annealing helps somewhat, but this distribution shift between what the predictor learns and what inference actually needs is significant and glossed over.

The Mistral-7B results are single-seed with no downstream task evaluation, yet the paper claims consistent cross-architecture benefits based only on PPL. Given the 9.5 percentage point standard deviation observed on MMLU at 30% sparsity with LLaMA, a single run on Mistral doesn't provide much confidence in that claim.

Finally, the "adaptive penalty controller" framing is misleading. The method uses a heuristic penalty schedule that resembles constrained optimization, but it's not actually solving a constrained problem—at 30% and 70% sparsity, λ hits its cap, meaning the controller fails to find a satisfactory solution and the constraint is only approximately satisfied.

The SNR analysis covers just 300 of 1000 training steps across 7 checkpoints. The non-monotonic behavior where BCE outperforms KL mid-training actually undermines the claim that KL has fundamentally better gradient structure—it looks more like a late-training convergence artifact than an inherent advantage. Measuring SNR across the full training trajectory would give a clearer picture.

A few other gaps stand out: the conclusion is just one sentence, WikiText-103 to WikiText-2 isn't a real out-of-distribution test since they're the same corpus (C4 is, but only at 2 sparsity levels), and there's an inconsistency between the exp_id for the 40% uniform entry and what the caption claims. For Qwen in Table 5, GSM8K results are missing for uniform entries without explanation.

Stepping back on the overall assessment: the KL distillation methodology itself is sound, but the evidence doesn't fully back the structural mismatch narrative because of confounding factors, and the missing intermediate-coupling baselines are a real gap—I'd rate soundness at 3/5. The problem matters practically and the compensation redundancy insight is useful, but the contribution feels somewhat incremental, and the Qwen-14B negative result tempers enthusiasm—excitement is also 3/5. The central narrative seems overfit to incomplete evidence, and the missing ShadowLLM and D2DMoE comparisons plus the Qwen MMLU gap are the most troubling gaps.

Settling on a score: the confounded comparison is genuinely problematic, and those missing baselines leave a significant hole in the argument. The paper is well-written with solid ablations and honest about limitations, and the compensation redundancy finding has practical value. The gradient analysis, while not conclusively proving the structural mismatch claim, is a reasonable starting point. I'm landing on 3.0—Findings-level—though there's an argument for 3.5. I'm fairly confident in this assessment, though I acknowledge I might be overcorrecting on the confound issue since the paper does flag it.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3b630fdc-95bc-447b-983e-556279c65c0b",
  "isSidechain": false,
  "requestId": "req_011CbA2kdWJEZhv8KBp6sDuQ",
  "type": "assistant",
  "uuid": "0120b25e-54ae-401b-877e-f42493a88935",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BQmJFZB73jy9uFP7Rx5f2s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13150,
      "cache_read_input_tokens": 57888,
      "output_tokens": 13106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13150,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13106,
          "cache_read_input_tokens": 57888,
          "cache_creation_input_tokens": 13150,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13150
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

_source line 57 · 2026-05-18T12:30:11.699Z_

引用验证完成（35/39 verified，4 minor mismatches 均为作者姓格式差异，无虚假引用）。现在编写完整审稿报告。

---

## 总体评分
**Overall**: 3.0 (Findings)
**Confidence**: 4/5 (Quite sure)
**一句话总结**: 实用的 KL 蒸馏方案替代 BCE 训练稀疏预测器，但核心 "structural mismatch" 叙事的因果证据不足——KL 与 BCE 的比较被多重流水线差异混淆，且缺少中间耦合度方法 (ShadowLLM/D2DMoE) 的关键 baseline。

---

## 官方维度打分（ACL ARR Review Form, Feb 2025+）

| 维度 | 分数 | 理由摘要 |
|------|------|----------|
| Soundness | 3.0/5 | 核心方法可行，但 BCE vs KL 比较存在未解混淆变量（oracle 来源、mask 类型、sparsity 控制方式同时不同）；"structural mismatch" 论证在严格意义上是循环论证 |
| Excitement | 3.0/5 | 问题实际相关，compensation 冗余发现实用，但贡献偏 incremental（替换一个 loss），Qwen-14B 的 MMLU 负结果削弱泛化故事 |
| Reproducibility | 4.0/5 | 超参数完整，训练/评估协议清晰，缺少代码但提供了充足细节 |
| Overall Assessment | 3.0 | Findings 水平——有扎实的实验工作和诚实的局限性讨论，但因果证据的缺口和缺失的 intermediate baseline 使核心 claim 证据不充分 |

---

## Paper Summary

论文提出用 forward KL 蒸馏替代 per-neuron BCE 来训练 SwiGLU LLM 的激活稀疏性预测器。核心论点是 BCE 的 per-neuron 梯度与 TEAL 的 global top-k 推理分配存在 "structural mismatch"：BCE 梯度独立于其他神经元，而 KL 梯度通过 Jacobian 耦合所有神经元。在 LLaMA-3.1-8B 上，一个 <1% 参数量的预测器在 30-70% 稀疏度下均优于 TEAL，且 compensation network 冗余。论文还分析了 allocation-downstream 交互效应和跨架构泛化（Mistral-7B、Qwen-2.5-14B）。

---

## 主要优势

1. **问题定义清晰且实际相关**：指出 per-neuron training 与 global inference allocation 之间的不匹配是一个真实的工程问题，从业者会遇到。

2. **Ablation 设计系统全面**：Table 3 逐一隔离 divergence direction、Gumbel vs STE、compensation 效果，覆盖面好。特别是 "BCE + Gumbel + Penalty" 的 loss isolation 实验和 divergence direction 比较有信息量。

3. **诚实的局限性讨论**：论文主动承认 KL vs BCE confound 未完全 disentangle（§4.3、Limitations）、Qwen-14B MMLU gap、single-seed 局限等，这在同类工作中少见。

4. **Compensation 冗余的实用价值**：证明 KL predictor 使 67.2M 参数的 compensation network 多余，同时减少 2.7% inference latency——这是直接可用的工程发现。

5. **Training 效率极高**：1000 步 / 45 分钟训练即可达到饱和（Appendix A.3 确认 800 步后几乎无提升），实际部署门槛很低。

---

## Must-Fix 问题（影响接收决定）

**N1** [critical] BCE 与 KL 比较存在多重混淆变量，不能支撑 "structural mismatch" 因果 claim

- **具体位置**：§3.6、§4.3、Table 3
- **问题**：KL 与 BCE 的比较存在至少四个同时变化的因素：(1) loss function (KL vs BCE)；(2) oracle 来源（output distribution vs magnitude-based threshold）；(3) mask 类型（Gumbel-Sigmoid 连续 vs hard threshold）；(4) sparsity 控制（adaptive penalty vs oracle 内建 threshold）。论文的 "loss isolation" ablation（Table 3: BCE + Gumbel + Penalty = PPL 38.02）并未清楚隔离 loss 效果——adaptive penalty 机制专为 KL-style 全局优化设计，对 BCE 的 per-neuron 目标产生干扰（论文自身也承认："the penalty interferes with per-neuron optimization without global coordination"）。真正的隔离实验应该是：(a) BCE trained on KL-derived oracle masks，或 (b) KL with magnitude-based oracle constraints。论文在 §4.3 和 Limitations 中明确提到 "an ablation using KL-derived masks as BCE targets would isolate the effect"，但未执行。
- **为什么影响接收**：论文的核心叙事（从 title 到 abstract 到 introduction）都建立在 "structural mismatch → KL coupling resolves it" 的因果链上。如果 KL 的优势主要来自直接优化正确的指标（output distribution）而非梯度耦合本身，那么论文的贡献从 "揭示结构性错配并通过梯度耦合解决" 降级为 "换了个 loss 效果更好"。当前证据无法区分这两种解释。
- **建议修改方向**：至少执行一个 oracle-swap ablation（用 KL 导出的 mask 作为 BCE target 重新训练 BCE predictor）。如果这也不可行，则在叙事上将 "structural mismatch" 从因果 claim 降级为 motivating hypothesis，并将贡献重新定位为 empirical finding。

**N2** [critical] 缺少 intermediate coupling (MSE) baseline 比较

- **具体位置**：Table 1 (taxonomy)、§2 Related Work
- **问题**：论文的 taxonomy 将方法分为 Decomposed (BCE)、Intermediate (MSE)、Coupled (KL) 三个耦合度级别。但实验只比较了两个极端（BCE vs KL），完全缺少 Intermediate level 的实验比较。ShadowLLM（per-token × MSE）和 D2DMoE（per-token × MSE）在 taxonomy 中被标注但从未作为 baseline 出现。如果 intermediate coupling 已经能获得 KL 的大部分优势，那么全 end-to-end KL 的额外复杂性（Gumbel relaxation、adaptive penalty、full forward pass gradient）就失去了正当性。
- **为什么影响接收**：Table 1 是论文自己建立的分析框架，但实验未覆盖框架中的关键象限。审稿人会直接追问：MSE hidden-state loss 作为 KL 和 BCE 之间的自然中间点，效果如何？
- **建议修改方向**：在相同实验条件下实现 MSE hidden-state loss baseline（per-layer MSE on FFN output, matching ShadowLLM/D2DMoE 的 supervision level）。如果实验资源不足，至少需要明确讨论为什么缺少此比较，并降低 taxonomy 的 claim 力度。

---

## Should-Fix 问题（影响评分但不一票否决）

**W1** [warning] "Three operating regions" 结论基于 3 个数据点

- **具体位置**：§4.5、Table 4
- **问题**：论文用 30/40/50% 三个稀疏度定义了 "budget-surplus / budget-constrained / capacity-limited" 三个 regime。3 个数据点拟合 3 个 regime 的自由度为零——任何 3 个有差异的点都能被划分成 3 类。此外 40% 数据全部是 single seed。论文虽然承认 "Denser sampling would be needed"，但仍将其作为正式发现呈现。
- **建议**：补充 25%、35%、45%、55% 中的至少 2 个点；或将此部分从 "finding" 降级为 "preliminary observation"。

**W2** [warning] 40% uniform PPL (8.36) 低于 30% uniform PPL (8.82) 的反直觉结果未讨论

- **具体位置**：Table 4
- **问题**：Table 4 显示 40% uniform PPL 8.36 < 30% uniform PPL 8.82。更高的稀疏度应该导致更高的 PPL。两者都使用 seed 42。可能的解释：30% target 的 penalty controller 饱和于 λ\_max=5000（Appendix C, Table 7），optimizer 被 penalty 主导导致 predictor 质量下降；而 40% target λ 收敛于 625（未饱和），optimizer 更健康。如果这是真实现象，它暗示 penalty controller 的设计缺陷在推荐的 30% operating point 实际损害了 predictor 质量——这需要讨论。
- **建议**：分析 30% vs 40% predictor 的 KL loss 分量（剥离 penalty 后的纯 KL），确认是否 penalty saturation 导致了这一反转。

**W3** [warning] 训练-推理 gap（soft → hard mask）未被量化讨论

- **具体位置**：§3.3、Appendix B (Table 6)
- **问题**：训练使用 Gumbel-Sigmoid 连续 mask，推理使用 TEAL hard top-k。Appendix B 的 per-token evaluation（使用 predictor 自己的 soft mask，无全局预算约束）给出 PPL 9.218（d\_b=128），而 TEAL global 给出 11.963——30% 的 gap。虽然这个 gap 混合了 soft→hard 和 per-token→global 两个效应，但 30% 的降幅说明 predictor 训练中学到的信号在推理时被部分浪费。温度退火（τ: 1.0→0.1）部分缓解但残差仍大。
- **建议**：在 §3.3 或 §4.4 中正式讨论此 gap，并量化 soft-mask-at-inference 与 hard-mask-at-inference 的性能差异。

**W4** [warning] Qwen-14B MMLU 降幅对论文 framing 的影响不足

- **具体位置**：§4.5、Table 5、Abstract
- **问题**：Qwen-14B 上 KL 的 MMLU 为 63.7%，而 TEAL/BCE 均 >71%——差距 8pp。Abstract 写 "confirms the PPL advantage across 7–14B, though 14B reveals a scale-dependent MMLU gap"，但 "PPL advantage" 的 framing 让读者容易忽略 MMLU 在实用场景中比 PPL 更重要。如果 KL predictor 在更大模型上系统性地以 PPL 换 MMLU，其实用价值大打折扣。
- **建议**：在 Abstract 中更对等地呈现 PPL 和 MMLU 的结果；在 §4.5 或 Discussion 中讨论为什么 KL 的 output-preservation objective 可能与 task-specific feature preservation 存在 trade-off（不仅是推测，应尝试提供机制解释，如 KL 对 high-entropy 区域过度关注而忽略低 entropy 但 task-critical 的 token 位置）。

**W5** [warning] Mistral-7B 跨架构验证仅有 PPL，无 downstream

- **具体位置**：§4.5、Table 5
- **问题**：论文声称 "preliminary evidence of generality at the 7-8B scale"，但 Mistral 仅报告 PPL。鉴于论文自身反复强调 "PPL is a poor proxy for reasoning ability"（§4.5 paragraph 2、Limitations），PPL-only 的跨架构验证与论文自己的立场矛盾。且全部 single seed，无 variance estimate。
- **建议**：至少在 30% sparsity 上报告 Mistral 的 MMLU 和 ARC-c。

**W6** [warning] SNR 分析仅覆盖前 300 步（总训练 1000 步）

- **具体位置**：§3.6、Appendix F
- **问题**：SNR 在 7 个 checkpoint（step 0-300）上测量，仅覆盖 30% 的训练过程。关键的非单调性（BCE 在 step 100-250 超过 KL）意味着 KL 的 SNR 优势是 late-training 现象，可能与收敛动态有关而非 "fundamental structural property"。完整的 1000 步 SNR trajectory 对于支撑叙事是必要的。
- **建议**：扩展 SNR 测量至 1000 步，确认 KL 的优势在后半段是否持续增长。

---

## 小问题（不影响接收）

- Conclusion 仅一句话，即使考虑空间限制也过于简略，建议至少增加未来方向的一句话指引
- WikiText-103 训练 → WikiText-2 评测并非真正的 OOD（同一语料不同 split），论文将 C4 归为 OOD（正确），但 C4 仅覆盖 30/50% 两个 sparsity level
- Table 4 中 40% uniform 的 exp\_id 为 `d030_kl40_uniform`，前缀 "d030" 暗示可能使用 30% 训练的 predictor 而非 40%——如果是这样，caption 中 "each row uses a predictor trained at the respective sparsity target" 有误
- Table 5 (Qwen-14B) 的 uniform allocation 行缺少 GSM8K 数据（标记为 "---"），未解释原因
- 引用验证显示 4 个 minor mismatch（作者姓格式差异），无虚假引用；`loshchilov2019adamw` 的年份 bib=2019 vs API=2017 需要统一（ICLR 2019 是发表年，2017 是 preprint 年）

---

## Missing References

- **ShadowLLM 和 D2DMoE 的实验比较**：虽然引用了这两篇，但作为 taxonomy 中 "Intermediate coupling" 的代表方法，缺少实验对比是严重遗漏
- 可考虑引用 **Griffin et al. (2024), "Towards Understanding Sparsity in Neural Networks"** 或类似的 sparsity-loss landscape 分析工作，为 soft→hard mask gap 提供理论背景

---

## Questions to Authors

1. Table 4 中 40% uniform PPL (8.36) 低于 30% uniform PPL (8.82)，请解释这一反直觉结果。exp\_id `d030_kl40_uniform` 中的 "d030" 是否意味着实际使用了 30% 训练的 predictor？

2. 是否有计划执行 oracle-swap ablation（用 KL-derived masks 作为 BCE target）？这是论文自身提出的关键实验（§4.3）。

3. Qwen-14B 上 KL 的 MMLU gap 是否在其他 downstream task 上也存在？Table 5 显示 ARC-c 和 WinoGrande 上 KL 与 TEAL/BCE 接近，那么 MMLU 的 gap 是否可能与 MMLU 的 knowledge-intensive 特性有关（如特定层的知识被稀疏化时丢失更多）？

4. Appendix B 中 per-token evaluation PPL（9.218）与 TEAL global PPL（11.963）的 30% gap 中，多少来自 soft→hard 转换，多少来自 per-token→global allocation 转换？一个 hard-mask + per-token 的 evaluation 即可分离这两个效应。

---

现在将审稿报告提交给 Review Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0120b25e-54ae-401b-877e-f42493a88935",
  "isSidechain": false,
  "requestId": "req_011CbA2kdWJEZhv8KBp6sDuQ",
  "type": "assistant",
  "uuid": "d9f7bd4c-180e-4880-92f4-2e3672bc55de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BQmJFZB73jy9uFP7Rx5f2s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13150,
      "cache_read_input_tokens": 57888,
      "output_tokens": 13106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13150,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13106,
          "cache_read_input_tokens": 57888,
          "cache_creation_input_tokens": 13150,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13150
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

_source line 58 · 2026-05-18T12:30:57.809Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_0188NNQWsbZBr3Mxw3YUYvVd`</summary>

```json
{
  "text": "## Round 7 Reviewer 1 审稿报告：方法严谨性 + 实验充分性\n\n## 总体评分\n**Overall**: 3.0 (Findings)\n**Confidence**: 4/5 (Quite sure)\n**一句话总结**: 实用的 KL 蒸馏方案替代 BCE 训练稀疏预测器，但核心 \"structural mismatch\" 叙事的因果证据不足——KL 与 BCE 的比较被多重流水线差异混淆，且缺少中间耦合度方法 (ShadowLLM/D2DMoE) 的关键 baseline。\n\n---\n\n## 官方维度打分（ACL ARR Review Form, Feb 2025+）\n\n| 维度 | 分数 | 理由摘要 |\n|------|------|----------|\n| Soundness | 3.0/5 | 核心方法可行，但 BCE vs KL 比较存在未解混淆变量（oracle 来源、mask 类型、sparsity 控制方式同时不同）；\"structural mismatch\" 论证在严格意义上是循环论证 |\n| Excitement | 3.0/5 | 问题实际相关，compensation 冗余发现实用，但贡献偏 incremental（替换一个 loss），Qwen-14B 的 MMLU 负结果削弱泛化故事 |\n| Reproducibility | 4.0/5 | 超参数完整，训练/评估协议清晰，缺少代码但提供了充足细节 |\n| Overall Assessment | 3.0 | Findings 水平——有扎实的实验工作和诚实的局限性讨论，但因果证据的缺口和缺失的 intermediate baseline 使核心 claim 证据不充分 |\n\n---\n\n## 主要优势\n\n1. **问题定义清晰且实际相关**：per-neuron training 与 global inference allocation 之间的不匹配是真实工程问题。\n\n2. **Ablation 设计系统全面**：Table 3 逐一隔离 divergence direction、Gumbel vs STE、compensation 效果。\n\n3. **诚实的局限性讨论**：主动承认 confound 未完全 disentangle、Qwen-14B MMLU gap、single-seed 局限。\n\n4. **Compensation 冗余的实用价值**：KL predictor 使 67.2M 参数 compensation network 冗余，减少 2.7% inference latency。\n\n5. **Training 效率极高**：1000 步/45 分钟训练达到饱和。\n\n---\n\n## Must-Fix 问题（影响接收决定）\n\n**N1** [critical] BCE 与 KL 比较存在多重混淆变量，不能支撑 \"structural mismatch\" 因果 claim\n\n- 具体位置：§3.6、§4.3、Table 3\n- 问题：KL 与 BCE 的比较存在至少四个同时变化的因素：(1) loss function；(2) oracle 来源（output distribution vs magnitude-based threshold）；(3) mask 类型（Gumbel-Sigmoid 连续 vs hard threshold）；(4) sparsity 控制（adaptive penalty vs oracle 内建 threshold）。论文的 \"loss isolation\" ablation（BCE + Gumbel + Penalty = PPL 38.02）并未清楚隔离 loss 效果——adaptive penalty 对 BCE per-neuron 目标产生干扰。关键缺失实验：(a) BCE trained on KL-derived oracle masks，或 (b) KL with magnitude-based oracle constraints。论文在 §4.3 和 Limitations 中承认此问题但未执行。\n- 影响：论文核心叙事建立在 \"structural mismatch → KL coupling resolves it\" 的因果链上。当前证据无法区分 \"梯度耦合本身有益\" 和 \"直接优化正确指标有益\" 两种解释。\n- 建议：执行 oracle-swap ablation；或将 \"structural mismatch\" 从因果 claim 降级为 motivating hypothesis。\n\n**N2** [critical] 缺少 intermediate coupling (MSE) baseline 比较\n\n- 具体位置：Table 1、§2 Related Work\n- 问题：Taxonomy 将方法分为 Decomposed/Intermediate/Coupled 三级，但实验只比较两个极端。ShadowLLM 和 D2DMoE（MSE, intermediate）从未作为 baseline。如果 intermediate coupling 已获得大部分优势，full end-to-end KL 的额外复杂性失去正当性。\n- 建议：实现 MSE hidden-state loss baseline；如资源不足，明确讨论此缺失。\n\n---\n\n## Should-Fix 问题（影响评分但不一票否决）\n\n**W1** [warning] \"Three operating regions\" 结论基于 3 个数据点\n\n- 具体位置：§4.5、Table 4\n- 30/40/50% 三点拟合三类 regime，自由度为零。40% 全部 single seed。\n- 建议：补充中间 sparsity 点或降级为 \"preliminary observation\"。\n\n**W2** [warning] 40% uniform PPL (8.36) 低于 30% uniform PPL (8.82) 的反直觉结果未讨论\n\n- 具体位置：Table 4\n- 更高稀疏度应导致更高 PPL。可能与 30% target penalty controller 饱和（λ→5000）导致 predictor 质量下降有关。\n- 建议：分析 30% vs 40% predictor 的纯 KL loss 分量。\n\n**W3** [warning] 训练-推理 gap（soft → hard mask）未被量化讨论\n\n- 具体位置：§3.3、Appendix B\n- Per-token evaluation PPL 9.218 vs TEAL global PPL 11.963——30% gap 未讨论。\n- 建议：正式讨论此 gap，量化 soft vs hard mask 的分离效应。\n\n**W4** [warning] Qwen-14B MMLU 降幅对论文 framing 影响不足\n\n- 具体位置：§4.5、Table 5、Abstract\n- KL MMLU 63.7% vs TEAL/BCE >71%。Abstract 以 \"PPL advantage\" 领衔，低估了实用场景中 MMLU 的重要性。\n- 建议：在 Abstract 中更对等呈现；讨论 KL output-preservation 与 task-specific feature preservation 的 trade-off 机制。\n\n**W5** [warning] Mistral-7B 仅 PPL 无 downstream\n\n- 论文反复强调 \"PPL is a poor proxy for reasoning\"，但 Mistral 跨架构验证仅有 PPL。\n- 建议：至少报告 Mistral 30% 的 MMLU 和 ARC-c。\n\n**W6** [warning] SNR 分析仅覆盖前 300/1000 步\n\n- 非单调性（BCE 在 step 100-250 超过 KL）意味着 KL SNR 优势是 late-training 现象，可能与收敛动态有关而非结构性质。\n- 建议：扩展至 1000 步完整 trajectory。\n\n---\n\n## 小问题\n\n- Conclusion 仅一句话\n- WikiText-103→WikiText-2 非真正 OOD；C4 仅覆盖 30/50%\n- 40% uniform exp_id `d030_kl40_uniform` 前缀暗示可能使用 30% predictor，与 caption 矛盾\n- Table 5 Qwen uniform 行缺少 GSM8K 数据未解释\n- 引用整体可靠（35/39 verified），4 个 minor mismatch 为作者姓格式差异\n\n---\n\n## Questions to Authors\n\n1. Table 4 中 40% uniform PPL (8.36) 低于 30% uniform PPL (8.82)，请解释。exp_id d030 是否意味着使用了 30% predictor？\n2. 是否计划执行 oracle-swap ablation？\n3. Qwen-14B MMLU gap 是否在其他 knowledge-intensive task 上也存在？\n4. Per-token PPL (9.218) 与 TEAL global PPL (11.963) 的 30% gap 中，soft→hard 和 per-token→global 各贡献多少？",
  "reviewer_id": "1",
  "project": "distill_sparse_swiglu"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d9f7bd4c-180e-4880-92f4-2e3672bc55de",
  "isSidechain": false,
  "requestId": "req_011CbA2kdWJEZhv8KBp6sDuQ",
  "type": "assistant",
  "uuid": "4f5e4c6b-b280-448a-90a5-f25e853d7d18",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BQmJFZB73jy9uFP7Rx5f2s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13150,
      "cache_read_input_tokens": 57888,
      "output_tokens": 13106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13150,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13106,
          "cache_read_input_tokens": 57888,
          "cache_creation_input_tokens": 13150,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13150
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

_source line 59_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Round 7 Reviewer 1，负责 **方法严谨性 + 实验充分性**。  ## Venue 信息 - **目标**: EMNLP 2026 (ARR May 2026 cycle) - **截止日期**: 2026-05-25 - **格式**: ACL style, Long paper ≤8 页正文, double-blind - **评分标准*…",
  "leafUuid": "4f5e4c6b-b280-448a-90a5-f25e853d7d18",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Runtime record

_source line 60_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Tool result

_source line 61 · 2026-05-18T12:31:02.922Z_

<details><summary>↩ Tool result · `toolu_0188NNQWsbZBr3Mxw3YUYvVd`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_ddde40053945c09c17d4aaa8ca8e5b93:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4f5e4c6b-b280-448a-90a5-f25e853d7d18",
  "isSidechain": false,
  "promptId": "e5c9a378-4434-4d1d-9fa1-4a199d25cd51",
  "type": "user",
  "uuid": "a84335a1-6766-4a8b-af11-f07f8b7bf781",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_ddde40053945c09c17d4aaa8ca8e5b93:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_ddde40053945c09c17d4aaa8ca8e5b93:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "4f5e4c6b-b280-448a-90a5-f25e853d7d18",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 62_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Runtime record

_source line 63 · 2026-05-18T12:32:02.474Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-18T12:32:02.474Z",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "content": "[Round 1 审稿请求]:\n以下是 Reviewer 2 的完整审稿意见。请逐条回应：[AGREE] 同意并说明理由，或 [REBUT] 反驳并提供证据（cite 具体 Section/Table/Figure）。\n\n---\n\n## Reviewer 2 完整审稿原文\n\n**Overall**: 3.0 (Findings), Confidence 4/5\n\n### 主要优势\nS1. 诚实透明的实验报告（负面结果坦诚呈现）\nS2. 系统性消融设计（Table 3 逐一隔离各因素）\nS3. 多种子统计和方差报告\nS4. 写作质量（无 AI 写作痕迹）\nS5. Gradient 分析提供清晰直觉\n\n### Must-Fix 问题\n\n**N1** [critical] 技术新颖性有限：已有组件的新问题组合\n- 核心技术组件（frozen weights + learnable masks + KL training + Gumbel relaxation）全部来自 MaskLLM。区分点是 N:M static weight sparsity vs dynamic per-token activation sparsity——problem formulation 层面的不同而非方法层面的创新。Table 1 taxonomy（2×3, 5/6 cells filled）填充空 cell 的新颖性论证较弱。论文自身定位 \"primarily empirical\"。\n\n**N2** [critical] Headline 数字与推荐操作点之间的叙事张力\n- 50% sparsity 的 \"49% PPL reduction\" 是 headline，但该 regime 下 downstream 全面崩溃。推荐操作点 30% 改善为 PPL 18%, MMLU +2.1pp，且 ARC-c (40.78 vs 42.32) 和 GSM8K (7.35 vs 7.88) 实际劣于 TEAL vanilla。Conclusion 仅一句以 \"halves PPL\" 为卖点——overclaiming。\n\n**N3** [critical] 14B 结果实质性削弱泛化 claim\n- Qwen-14B MMLU 比 TEAL 低 8.1pp，比 BCE 低 7.95pp。Uniform 仅恢复 +0.8pp。Abstract 称 \"confirms the PPL advantage\" 将严重退化轻描淡写。\n\n### Should-Fix 问题\n\n**W1** BCE 对比存在混淆变量（oracle 质量 vs 训练目标）\n**W2** 无实际推理加速（+6.4% overhead, unstructured masks）\n**W3** Conclusion 过于简短（一句话）\n**W4** `\\enlargethispage{8\\baselineskip}` 页面操纵（≈1.3 inches expansion）\n**W5** \"Structural mismatch\" 洞察本质是标准链式法则应用\n\n### 小问题\nM1: Table 2/4 高度重叠\nM2: 39 篇引用处于下限\nM3: 术语不一致\nM4: \"We provide this analysis.\" 突兀\nM5: exp_id 注释未清除\n\n### Questions\nQ1: 30% uniform 在 ARC-c/GSM8K 劣于 TEAL，为何仍推荐？\nQ2: 14B MMLU 退化能否通过 temperature 调整或混合 loss 缓解？\nQ3: MaskLLM Gumbel-Softmax vs 本文 Gumbel-Sigmoid 在优化 landscape 上有什么实质区别？\nQ4: KL-derived masks 作 BCE targets 的 ablation 是否有初步结果？\n\n### Missing References\n1. Quantization + Sparsity（AWQ, SqueezeLLM）\n2. Dynamic inference 综述（Schuster et al., Han et al.）\n3. FLAP（fluctuation-based activation pruning）\n4. LLM-Pruner（structured pruning with gradient）\n\n---\n\n请对以上每个 Must-Fix (N1, N2, N3)、Should-Fix (W1-W5)、小问题 (M1-M5)、Questions (Q1-Q4)、和 Missing References 逐条给出 [AGREE] 或 [REBUT] 回应。"
}
```

---

### Runtime record

_source line 64 · 2026-05-18T12:32:02.475Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-18T12:32:02.475Z",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

## Round 2

2 recorded events

### User

_source line 65 · 2026-05-18T12:32:02.464Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a84335a1-6766-4a8b-af11-f07f8b7bf781",
  "isSidechain": false,
  "promptId": "a88c61fa-486d-4ffb-93ed-ff9cfd47dd27",
  "type": "user",
  "isMeta": true,
  "uuid": "1adc8a0b-16f1-4b67-875d-f8a0559136d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 66 · 2026-05-18T12:32:02.464Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1adc8a0b-16f1-4b67-875d-f8a0559136d2",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "4e2584ea-2ff3-4815-b3a5-6b7bf1d3defc",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "id": "fffc4444-7c9f-48b9-9c46-2f0c7e66b3a9",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---

## Round 3

3 recorded events

### User

_source line 67 · 2026-05-18T12:32:02.572Z_

[Round 1 审稿请求]:
以下是 Reviewer 2 的完整审稿意见。请逐条回应：[AGREE] 同意并说明理由，或 [REBUT] 反驳并提供证据（cite 具体 Section/Table/Figure）。

---

## Reviewer 2 完整审稿原文

**Overall**: 3.0 (Findings), Confidence 4/5

### 主要优势
S1. 诚实透明的实验报告（负面结果坦诚呈现）
S2. 系统性消融设计（Table 3 逐一隔离各因素）
S3. 多种子统计和方差报告
S4. 写作质量（无 AI 写作痕迹）
S5. Gradient 分析提供清晰直觉

### Must-Fix 问题

**N1** [critical] 技术新颖性有限：已有组件的新问题组合
- 核心技术组件（frozen weights + learnable masks + KL training + Gumbel relaxation）全部来自 MaskLLM。区分点是 N:M static weight sparsity vs dynamic per-token activation sparsity——problem formulation 层面的不同而非方法层面的创新。Table 1 taxonomy（2×3, 5/6 cells filled）填充空 cell 的新颖性论证较弱。论文自身定位 "primarily empirical"。

**N2** [critical] Headline 数字与推荐操作点之间的叙事张力
- 50% sparsity 的 "49% PPL reduction" 是 headline，但该 regime 下 downstream 全面崩溃。推荐操作点 30% 改善为 PPL 18%, MMLU +2.1pp，且 ARC-c (40.78 vs 42.32) 和 GSM8K (7.35 vs 7.88) 实际劣于 TEAL vanilla。Conclusion 仅一句以 "halves PPL" 为卖点——overclaiming。

**N3** [critical] 14B 结果实质性削弱泛化 claim
- Qwen-14B MMLU 比 TEAL 低 8.1pp，比 BCE 低 7.95pp。Uniform 仅恢复 +0.8pp。Abstract 称 "confirms the PPL advantage" 将严重退化轻描淡写。

### Should-Fix 问题

**W1** BCE 对比存在混淆变量（oracle 质量 vs 训练目标）
**W2** 无实际推理加速（+6.4% overhead, unstructured masks）
**W3** Conclusion 过于简短（一句话）
**W4** `\enlargethispage{8\baselineskip}` 页面操纵（≈1.3 inches expansion）
**W5** "Structural mismatch" 洞察本质是标准链式法则应用

### 小问题
M1: Table 2/4 高度重叠
M2: 39 篇引用处于下限
M3: 术语不一致
M4: "We provide this analysis." 突兀
M5: exp_id 注释未清除

### Questions
Q1: 30% uniform 在 ARC-c/GSM8K 劣于 TEAL，为何仍推荐？
Q2: 14B MMLU 退化能否通过 temperature 调整或混合 loss 缓解？
Q3: MaskLLM Gumbel-Softmax vs 本文 Gumbel-Sigmoid 在优化 landscape 上有什么实质区别？
Q4: KL-derived masks 作 BCE targets 的 ablation 是否有初步结果？

### Missing References
1. Quantization + Sparsity（AWQ, SqueezeLLM）
2. Dynamic inference 综述（Schuster et al., Han et al.）
3. FLAP（fluctuation-based activation pruning）
4. LLM-Pruner（structured pruning with gradient）

---

请对以上每个 Must-Fix (N1, N2, N3)、Should-Fix (W1-W5)、小问题 (M1-M5)、Questions (Q1-Q4)、和 Missing References 逐条给出 [AGREE] 或 [REBUT] 回应。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4e2584ea-2ff3-4815-b3a5-6b7bf1d3defc",
  "isSidechain": false,
  "promptId": "a88c61fa-486d-4ffb-93ed-ff9cfd47dd27",
  "type": "user",
  "uuid": "27ed2405-3bb2-4cfc-9abc-d856b984f13a",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/.claude/sessions/review_reviewer_1_772f066c",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 68_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 以下是 Reviewer 2 的完整审稿意见。请逐条回应：[AGREE] 同意并说明理由，或 [REBUT] 反驳并提供证据（cite 具体 Section/Table/Figure）。  ---  ## Reviewer 2 完整审稿原文  **Overall**: 3.0 (Findings), Confidence 4/5  ### 主要优势 S1. 诚实透明…",
  "leafUuid": "27ed2405-3bb2-4cfc-9abc-d856b984f13a",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

### Runtime record

_source line 69_

```json
{
  "type": "ai-title",
  "aiTitle": "Review methodology rigor and experimental sufficiency for SwiGLU sparsity predictor paper",
  "sessionId": "5312a086-3c80-45ff-89ba-6f1086157f10"
}
```

---

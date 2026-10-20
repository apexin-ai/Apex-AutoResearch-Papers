# Research conversation: [Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1 **审查侧重：方法严谨性 + 实验验证** ### 论文信息 - **标题**: Multi-Class Annotation Errors in C

**Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 87
- **Recorded user turns:** 5
- **Tool calls:** 21
- **Original source:** `logs/chats/exported-trajectories/account-3/e4d002b6-0100-4dfb-b117-a3b684ce7ac5.jsonl`
- **Structured JSON:** [`cb21d84bc3e66fec8f76.json`](../../sessions/cb/cb21d84bc3e66fec8f76.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-22T16:54:09.798Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-22T16:54:09.798Z",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "content": "[Round 1 审稿请求]:\n## Round 1 审稿任务 — Reviewer 1\n\n**审查侧重：方法严谨性 + 实验验证**\n\n### 论文信息\n- **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction\n- **论文路径**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex`\n- **PDF**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/submitted.pdf`\n- **目标 venue**: EMNLP 2026 (via ARR)\n- **投稿类别**: Long Paper\n- **Deadline**: 2026-05-25\n\n### Venue 格式要求\n- 正文 ≤ 8 页（不含 references、limitations、ethics）\n- ACL 模板（review 模式）\n- Double-blind 匿名审稿\n- ARR 统一审稿系统\n\n### 你的审查重点\n\n请重点审查以下方面：\n\n1. **理论正确性**：\n   - Proposition 1（sign preservation）的证明是否完整、严谨？条件是否充分？\n   - Theorem 1（envelope monotonicity）的证明是否成立？proof sketch 是否有逻辑漏洞？\n   - Conjecture 1 的数值验证是否充分？ε bound 是否合理？\n   - Eq.(1)-(3) 的推导是否正确？\n\n2. **实验设计**：\n   - 100,000 Dirichlet 矩阵的采样是否充分代表实际场景？\n   - Theory-MC agreement（MAPE 2.0%）的验证方法是否可靠？\n   - 实证验证（23 LLM configurations × 7 topologies）的覆盖是否充分？\n   - Correction methods 比较（210 configurations）是否公平？\n\n3. **FWL invariance 论证**：\n   - 0% bias reduction 的结论是否严格成立？\n   - 证明路径（column space preservation）是否完备？\n\n4. **假设合理性**：\n   - Non-differential misclassification 假设在 LLM 场景下是否合理？\n   - Linear SEM 假设的限制是否充分讨论？\n\n请按以下格式输出审稿意见：\n- **Summary**（2-3 句）\n- **Strengths**（逐条）\n- **Weaknesses**（逐条，标注 [CRITICAL] / [MAJOR] / [MINOR]）\n- **Questions**（需要作者回答的问题）\n- **Missing References**（遗漏的重要相关工作）\n- **Overall Assessment**（评分 + 置信度）\n\n评分标准（EMNLP 2026 ARR）：5=Consider for Award, 4.5=Borderline Award, 4=Conference, 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1.5=Resubmit after next cycle, 1=Do not resubmit"
}
```

---

### Runtime record

_source line 2 · 2026-05-22T16:54:09.823Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-22T16:54:09.823Z",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

## Round 1

7 recorded events

### User

_source line 3 · 2026-05-22T16:54:12.022Z_

[Round 1 审稿请求]:
## Round 1 审稿任务 — Reviewer 1

**审查侧重：方法严谨性 + 实验验证**

### 论文信息
- **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction
- **论文路径**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex`
- **PDF**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/submitted.pdf`
- **目标 venue**: EMNLP 2026 (via ARR)
- **投稿类别**: Long Paper
- **Deadline**: 2026-05-25

### Venue 格式要求
- 正文 ≤ 8 页（不含 references、limitations、ethics）
- ACL 模板（review 模式）
- Double-blind 匿名审稿
- ARR 统一审稿系统

### 你的审查重点

请重点审查以下方面：

1. **理论正确性**：
   - Proposition 1（sign preservation）的证明是否完整、严谨？条件是否充分？
   - Theorem 1（envelope monotonicity）的证明是否成立？proof sketch 是否有逻辑漏洞？
   - Conjecture 1 的数值验证是否充分？ε bound 是否合理？
   - Eq.(1)-(3) 的推导是否正确？

2. **实验设计**：
   - 100,000 Dirichlet 矩阵的采样是否充分代表实际场景？
   - Theory-MC agreement（MAPE 2.0%）的验证方法是否可靠？
   - 实证验证（23 LLM configurations × 7 topologies）的覆盖是否充分？
   - Correction methods 比较（210 configurations）是否公平？

3. **FWL invariance 论证**：
   - 0% bias reduction 的结论是否严格成立？
   - 证明路径（column space preservation）是否完备？

4. **假设合理性**：
   - Non-differential misclassification 假设在 LLM 场景下是否合理？
   - Linear SEM 假设的限制是否充分讨论？

请按以下格式输出审稿意见：
- **Summary**（2-3 句）
- **Strengths**（逐条）
- **Weaknesses**（逐条，标注 [CRITICAL] / [MAJOR] / [MINOR]）
- **Questions**（需要作者回答的问题）
- **Missing References**（遗漏的重要相关工作）
- **Overall Assessment**（评分 + 置信度）

评分标准（EMNLP 2026 ARR）：5=Consider for Award, 4.5=Borderline Award, 4=Conference, 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1.5=Resubmit after next cycle, 1=Do not resubmit

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "f7ef8805-df5b-4176-bb42-ab8305991a5a",
  "type": "user",
  "uuid": "7cabdcbf-4fda-4dd4-9ab2-fa75e7ad662d",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-22T16:54:12.012Z_

```json
{
  "parentUuid": "7cabdcbf-4fda-4dd4-9ab2-fa75e7ad662d",
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
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch"
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
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "299ef289-2f8f-4be7-8d1d-91e1be241aee",
  "timestamp": "2026-05-22T16:54:12.012Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-22T16:54:12.021Z_

```json
{
  "parentUuid": "299ef289-2f8f-4be7-8d1d-91e1be241aee",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "af323c55-3d3d-4bee-a9cd-c992b529a577",
  "timestamp": "2026-05-22T16:54:12.021Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 6 · 2026-05-22T16:54:12.748Z_

You've hit your limit · resets 4pm (UTC)

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "af323c55-3d3d-4bee-a9cd-c992b529a577",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "24ff6eb9-ed85-4c31-ae72-276204f4e119",
  "error": "rate_limit",
  "isApiErrorMessage": true,
  "apiErrorStatus": 429,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "id": "f26fe584-6bcd-4471-b796-f60b80790bae",
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

### Runtime record

_source line 7_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "24ff6eb9-ed85-4c31-ae72-276204f4e119",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Runtime record

_source line 8 · 2026-05-22T16:54:25.818Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-22T16:54:25.818Z",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "content": "[Round 1 审稿请求]:\n## Round 1 审稿任务 — Reviewer 1\n\n**审查侧重：方法严谨性 + 实验验证**\n\n### 论文信息\n- **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction\n- **论文路径**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex`\n- **PDF**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/submitted.pdf`\n- **目标 venue**: EMNLP 2026 (via ARR)\n- **投稿类别**: Long Paper\n- **Deadline**: 2026-05-25\n\n### Venue 格式要求\n- 正文 ≤ 8 页（不含 references、limitations、ethics）\n- ACL 模板（review 模式）\n- Double-blind 匿名审稿\n- ARR 统一审稿系统\n\n### 你的审查重点\n\n请重点审查以下方面：\n\n1. **理论正确性**：\n   - Proposition 1（sign preservation）的证明是否完整、严谨？条件是否充分？\n   - Theorem 1（envelope monotonicity）的证明是否成立？proof sketch 是否有逻辑漏洞？\n   - Conjecture 1 的数值验证是否充分？ε bound 是否合理？\n   - Eq.(1)-(3) 的推导是否正确？\n\n2. **实验设计**：\n   - 100,000 Dirichlet 矩阵的采样是否充分代表实际场景？\n   - Theory-MC agreement（MAPE 2.0%）的验证方法是否可靠？\n   - 实证验证（23 LLM configurations × 7 topologies）的覆盖是否充分？\n   - Correction methods 比较（210 configurations）是否公平？\n\n3. **FWL invariance 论证**：\n   - 0% bias reduction 的结论是否严格成立？\n   - 证明路径（column space preservation）是否完备？\n\n4. **假设合理性**：\n   - Non-differential misclassification 假设在 LLM 场景下是否合理？\n   - Linear SEM 假设的限制是否充分讨论？\n\n请按以下格式输出审稿意见：\n- **Summary**（2-3 句）\n- **Strengths**（逐条）\n- **Weaknesses**（逐条，标注 [CRITICAL] / [MAJOR] / [MINOR]）\n- **Questions**（需要作者回答的问题）\n- **Missing References**（遗漏的重要相关工作）\n- **Overall Assessment**（评分 + 置信度）\n\n评分标准（EMNLP 2026 ARR）：5=Consider for Award, 4.5=Borderline Award, 4=Conference, 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1.5=Resubmit after next cycle, 1=Do not resubmit"
}
```

---

### Runtime record

_source line 9 · 2026-05-22T16:54:25.819Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-22T16:54:25.819Z",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

## Round 2

2 recorded events

### User

_source line 10 · 2026-05-22T16:54:25.775Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "24ff6eb9-ed85-4c31-ae72-276204f4e119",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "isMeta": true,
  "uuid": "1eb8a7cb-12dc-4c14-873e-4164d00376c6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-22T16:54:25.779Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1eb8a7cb-12dc-4c14-873e-4164d00376c6",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "755d0a01-3113-4e1e-8c92-cbf8a126f952",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "id": "13e1de5c-9a18-4d37-a604-cdecba4df5a3",
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

67 recorded events

### User

_source line 12 · 2026-05-22T16:54:28.543Z_

[Round 1 审稿请求]:
## Round 1 审稿任务 — Reviewer 1

**审查侧重：方法严谨性 + 实验验证**

### 论文信息
- **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction
- **论文路径**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex`
- **PDF**: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/submitted.pdf`
- **目标 venue**: EMNLP 2026 (via ARR)
- **投稿类别**: Long Paper
- **Deadline**: 2026-05-25

### Venue 格式要求
- 正文 ≤ 8 页（不含 references、limitations、ethics）
- ACL 模板（review 模式）
- Double-blind 匿名审稿
- ARR 统一审稿系统

### 你的审查重点

请重点审查以下方面：

1. **理论正确性**：
   - Proposition 1（sign preservation）的证明是否完整、严谨？条件是否充分？
   - Theorem 1（envelope monotonicity）的证明是否成立？proof sketch 是否有逻辑漏洞？
   - Conjecture 1 的数值验证是否充分？ε bound 是否合理？
   - Eq.(1)-(3) 的推导是否正确？

2. **实验设计**：
   - 100,000 Dirichlet 矩阵的采样是否充分代表实际场景？
   - Theory-MC agreement（MAPE 2.0%）的验证方法是否可靠？
   - 实证验证（23 LLM configurations × 7 topologies）的覆盖是否充分？
   - Correction methods 比较（210 configurations）是否公平？

3. **FWL invariance 论证**：
   - 0% bias reduction 的结论是否严格成立？
   - 证明路径（column space preservation）是否完备？

4. **假设合理性**：
   - Non-differential misclassification 假设在 LLM 场景下是否合理？
   - Linear SEM 假设的限制是否充分讨论？

请按以下格式输出审稿意见：
- **Summary**（2-3 句）
- **Strengths**（逐条）
- **Weaknesses**（逐条，标注 [CRITICAL] / [MAJOR] / [MINOR]）
- **Questions**（需要作者回答的问题）
- **Missing References**（遗漏的重要相关工作）
- **Overall Assessment**（评分 + 置信度）

评分标准（EMNLP 2026 ARR）：5=Consider for Award, 4.5=Borderline Award, 4=Conference, 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1.5=Resubmit after next cycle, 1=Do not resubmit

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "755d0a01-3113-4e1e-8c92-cbf8a126f952",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "874b2b15-78f8-4a48-bc66-cdd06b743b7e",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 13 · 2026-05-22T16:54:33.740Z_

<details><summary>Logged reasoning block</summary>

```text
The user is asking me to perform a Round 1 review of a paper as Reviewer 1. Let me follow the instructions in my session CLAUDE.md:

1. First, I need to do Step 0 - search for EMNLP 2026 / ACL ARR reviewer guidelines
2. Then read the paper (PDF and/or tex files)
3. Produce the review

Let me start by:
1. Searching for venue reviewer guidelines
2. Reading the paper PDF/tex

Let me begin by loading the review-reviewer-session-start skill and searching for reviewer guidelines, then reading the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "874b2b15-78f8-4a48-bc66-cdd06b743b7e",
  "isSidechain": false,
  "requestId": "req_011CbHxUAUE2yhLkmcQnDsNG",
  "type": "assistant",
  "uuid": "3e954e10-675e-419b-b84f-f8bb730c0384",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016RBGiTGJNWQD9oi8rKG472",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17033,
      "cache_read_input_tokens": 11841,
      "output_tokens": 488,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17033,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 488,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 17033,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17033
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

_source line 14 · 2026-05-22T16:54:34.238Z_

开始执行 Round 1 审稿。先搜索 ARR reviewer guidelines，同时读取论文。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3e954e10-675e-419b-b84f-f8bb730c0384",
  "isSidechain": false,
  "requestId": "req_011CbHxUAUE2yhLkmcQnDsNG",
  "type": "assistant",
  "uuid": "850a9339-d09f-489e-8910-42dc5b2ab5e1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016RBGiTGJNWQD9oi8rKG472",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17033,
      "cache_read_input_tokens": 11841,
      "output_tokens": 488,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17033,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 488,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 17033,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17033
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

_source line 15 · 2026-05-22T16:54:38.609Z_

<details open><summary>🔧 Tool call — Agent · `toolu_01YR1v4iSg1Vtr4w12rjoKeL`</summary>

```json
{
  "description": "Search ARR reviewer guidelines",
  "subagent_type": "Explore",
  "prompt": "Search the web for \"ACL ARR 2025 2026 reviewer guidelines review form criteria\" and \"EMNLP 2026 reviewer guidelines scoring rubric\". I need to find the official ACL Rolling Review (ARR) review form dimensions and scoring criteria used for EMNLP 2026 submissions. Look for:\n1. The official review form fields and their scales (e.g., soundness, excitement, etc.)\n2. The scoring rubric for each dimension\n3. Any specific instructions for reviewers\n\nTry multiple search queries if needed. Report back all the official dimensions, scales, and criteria you find."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "850a9339-d09f-489e-8910-42dc5b2ab5e1",
  "isSidechain": false,
  "requestId": "req_011CbHxUAUE2yhLkmcQnDsNG",
  "type": "assistant",
  "uuid": "e8255f1e-0d73-4953-aad1-311487a8d535",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016RBGiTGJNWQD9oi8rKG472",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17033,
      "cache_read_input_tokens": 11841,
      "output_tokens": 488,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17033,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 488,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 17033,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17033
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

_source line 16 · 2026-05-22T16:54:38.872Z_

<details open><summary>🔧 Tool call — Read · `toolu_01E9SRNyEaJ7Poq6WJuqkFKA`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e8255f1e-0d73-4953-aad1-311487a8d535",
  "isSidechain": false,
  "requestId": "req_011CbHxUAUE2yhLkmcQnDsNG",
  "type": "assistant",
  "uuid": "a25ab97d-9c65-413b-8b4c-682a68cb713f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016RBGiTGJNWQD9oi8rKG472",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17033,
      "cache_read_input_tokens": 11841,
      "output_tokens": 488,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17033,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 488,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 17033,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17033
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

_source line 17 · 2026-05-22T16:54:39.069Z_

<details><summary>↩ Tool result · `toolu_01E9SRNyEaJ7Poq6WJuqkFKA`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	
4	\usepackage{graphicx}
5	\usepackage{algorithm}
6	\usepackage{algorithmic}
7	
8	\usepackage{amsmath,amssymb,amsthm}
9	\usepackage{booktabs}
10	\usepackage{pifont}
11	\usepackage{multirow}
12	
13	\newtheorem{definition}{Definition}
14	\newtheorem{proposition}{Proposition}
15	\newtheorem{theorem}{Theorem}
16	\newtheorem{lemma}{Lemma}
17	\newtheorem{conjecture}{Conjecture}
18	
19	\setlength{\textfloatsep}{8pt plus 2pt minus 4pt}
20	\setlength{\dbltextfloatsep}{8pt plus 2pt minus 4pt}
21	\setlength{\floatsep}{8pt plus 2pt minus 4pt}
22	\setlength{\dblfloatsep}{8pt plus 2pt minus 4pt}
23	\graphicspath{{../../figures/paper/}}
24	
25	\title{Multi-Class Annotation Errors in Causal Inference:\\Topology-Dependent Bias, Sensitivity, and Correction}
26	
27	\author{Anonymous}
28	
29	\begin{document}
30	\maketitle
31	
32	\input{abstract}
33	
34	\input{introduction}
35	
36	\input{related_work}
37	
38	\input{method}
39	
40	% ── Figures ──
41	
42	\begin{figure*}[t]
43	\centering
44	\includegraphics[width=0.92\textwidth,height=0.18\textheight,keepaspectratio]{fig1_dag_taxonomy.pdf}
45	\vspace{-6pt}
46	\caption{Seven canonical DAG topologies with starred-node annotation. $A$ (latent) connects to $A^*$ (observed) via a dashed measurement edge; the causal role of $A$ varies across topologies.}
47	\label{fig:dag_taxonomy}
48	\end{figure*}
49	
50	\begin{figure*}[t]
51	\centering
52	\includegraphics[width=0.92\textwidth,height=0.18\textheight,keepaspectratio]{fig2_bias_distribution.pdf}
53	\vspace{-6pt}
54	\caption{Bias distributions under 100{,}000 random $K{=}3$ confusion matrices. Red = sign reversal. Exposure: 83.4\% sign reversal; IV: 52.6\%.}
55	\label{fig:bias_distribution}
56	\end{figure*}
57	
58	\input{experiments}
59	
60	\input{conclusion}
61	
62	\bibliography{references}
63	
64	\appendix
65	\input{appendix_proofs}
66	
67	\end{document}
68	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a25ab97d-9c65-413b-8b4c-682a68cb713f",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "5eed3aad-f486-4344-aa27-63afdbae0284",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\n\\usepackage{graphicx}\n\\usepackage{algorithm}\n\\usepackage{algorithmic}\n\n\\usepackage{amsmath,amssymb,amsthm}\n\\usepackage{booktabs}\n\\usepackage{pifont}\n\\usepackage{multirow}\n\n\\newtheorem{definition}{Definition}\n\\newtheorem{proposition}{Proposition}\n\\newtheorem{theorem}{Theorem}\n\\newtheorem{lemma}{Lemma}\n\\newtheorem{conjecture}{Conjecture}\n\n\\setlength{\\textfloatsep}{8pt plus 2pt minus 4pt}\n\\setlength{\\dbltextfloatsep}{8pt plus 2pt minus 4pt}\n\\setlength{\\floatsep}{8pt plus 2pt minus 4pt}\n\\setlength{\\dblfloatsep}{8pt plus 2pt minus 4pt}\n\\graphicspath{{../../figures/paper/}}\n\n\\title{Multi-Class Annotation Errors in Causal Inference:\\\\Topology-Dependent Bias, Sensitivity, and Correction}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{method}\n\n% ── Figures ──\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.92\\textwidth,height=0.18\\textheight,keepaspectratio]{fig1_dag_taxonomy.pdf}\n\\vspace{-6pt}\n\\caption{Seven canonical DAG topologies with starred-node annotation. $A$ (latent) connects to $A^*$ (observed) via a dashed measurement edge; the causal role of $A$ varies across topologies.}\n\\label{fig:dag_taxonomy}\n\\end{figure*}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.92\\textwidth,height=0.18\\textheight,keepaspectratio]{fig2_bias_distribution.pdf}\n\\vspace{-6pt}\n\\caption{Bias distributions under 100{,}000 random $K{=}3$ confusion matrices. Red = sign reversal. Exposure: 83.4\\% sign reversal; IV: 52.6\\%.}\n\\label{fig:bias_distribution}\n\\end{figure*}\n\n\\input{experiments}\n\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{appendix_proofs}\n\n\\end{document}\n",
      "numLines": 68,
      "startLine": 1,
      "totalLines": 68
    }
  },
  "sourceToolAssistantUUID": "a25ab97d-9c65-413b-8b4c-682a68cb713f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-22T16:55:05.130Z_

<details><summary>↩ Tool result · `toolu_01YR1v4iSg1Vtr4w12rjoKeL`</summary>

```text
Perfect! I've found comprehensive information about the official ACL ARR review form and guidelines. Let me provide you with the complete findings:

## Official ACL ARR 2025-2026 Review Form Dimensions and Scoring Criteria

### Primary Scoring Dimensions (as of February 2025)

The official ACL Rolling Review uses **three main scoring components**:

#### 1. **Soundness** (1-5 scale, with half-point increments)
- 5: Excellent - thorough study for its type
- 4: Strong - sufficient support for all claims
- 3: Acceptable - supports main claims with minor gaps
- 2: Poor - main claims lack sufficient support
- 1: Major issues - not ready for publication

*Guidance: "Given that this is a short/long paper, is it sufficiently sound and thorough? Does it clearly state scientific claims and provide adequate support for them?"*

#### 2. **Excitement** (1-5 scale, with half-point increments)
- 5: Highly exciting - would recommend to others/attend presentation
- 4: Exciting - would mention to others
- 3: Interesting - might mention to others
- 2: Potentially interesting - may resonate with some
- 1: Not exciting - not relevant to NLP community

*Guidance: "How exciting is this paper for you?"*

#### 3. **Overall Assessment/Recommendation** (1-5 scale, with half-point increments)
- 5: Consider for award
- 4: Conference acceptance
- 3: Findings acceptance
- 2: Resubmit next cycle
- 1: Do not resubmit

*Guidance: Composite score reflecting soundness, excitement, and other factors like novelty and impact*

### Additional Evaluation Dimensions

#### 4. **Reviewer Confidence** (1-5 scale)
- 5: Positive evaluation; read carefully, familiar with related work
- 4: Quite sure; checked important points carefully
- 3: Pretty sure; good general familiarity but didn't check all details
- 2: Willing to defend evaluation; likely missed some details
- 1: Outside area or paper very difficult to understand

#### 5. **Reproducibility** (1-5 scale)
- 5: Results easily reproducible
- 4: Mostly reproducible with minor variations
- 3: Reproducible with difficulty
- 2: Hard to reproduce
- 1: Cannot reproduce

#### 6. **Datasets & Software** (1-5 scale each)
- 5: Enabling - affects research project choices
- 4: Useful - recommended for ongoing work
- 3: Potentially useful
- 2: Documentary - useful for replication
- 1: Not released

#### 7. **Author Identity Knowledge** (1-5 scale)
- 5: Know author from double-blind violation
- 4: Know from preprint/workshop
- 3: Know from submission contents
- 2: Know from informal communication
- 1: No educated guess

### Key Reviewer Guidelines for 2025-2026

**Critical Requirements:**
- Soundness scores MUST be justified by the text of the review
- Read papers twice (skim, then in-depth) to avoid bias
- Be specific with criticisms rather than vague generalizations
- Maintain professional, neutral tone (guidelines emphasize "a good review should be professional and neutral, if not kind")
- Distinguish between actual weaknesses and personal preferences
- Don't request unnecessary experiments beyond what claims require

**Important Policy Note:** Starting in May 2025, ARR adopts enforcement against "highly irresponsible" reviewing, including extremely terse reviews, unprofessional tone, and LLM-generated reviews. Violators may have work desk-rejected and be ineligible for resubmission.

### EMNLP 2026 Specifics

EMNLP 2026 submissions will use the ARR system with the same review form dimensions and criteria above. Review deadlines for EMNLP 2026 are July 6, 2026.

Sources:
- [ARR Reviewer Guidelines](http://aclrollingreview.org/reviewerguidelines)
- [ACL Rolling Review Form](http://aclrollingreview.org/reviewform)
- [ARR Area Chair Guidelines](http://aclrollingreview.org/acguidelines)
- [EMNLP 2026 FAQ](https://2026.emnlp.org/faq/)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e8255f1e-0d73-4953-aad1-311487a8d535",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "4714ac20-b4f3-4e09-ac88-9b5b38e5ab43",
  "toolUseResult": {
    "status": "completed",
    "prompt": "Search the web for \"ACL ARR 2025 2026 reviewer guidelines review form criteria\" and \"EMNLP 2026 reviewer guidelines scoring rubric\". I need to find the official ACL Rolling Review (ARR) review form dimensions and scoring criteria used for EMNLP 2026 submissions. Look for:\n1. The official review form fields and their scales (e.g., soundness, excitement, etc.)\n2. The scoring rubric for each dimension\n3. Any specific instructions for reviewers\n\nTry multiple search queries if needed. Report back all the official dimensions, scales, and criteria you find.",
    "agentId": "a9f9c8efcb745000f",
    "agentType": "Explore",
    "content": [
      {
        "type": "text",
        "text": "Perfect! I've found comprehensive information about the official ACL ARR review form and guidelines. Let me provide you with the complete findings:\n\n## Official ACL ARR 2025-2026 Review Form Dimensions and Scoring Criteria\n\n### Primary Scoring Dimensions (as of February 2025)\n\nThe official ACL Rolling Review uses **three main scoring components**:\n\n#### 1. **Soundness** (1-5 scale, with half-point increments)\n- 5: Excellent - thorough study for its type\n- 4: Strong - sufficient support for all claims\n- 3: Acceptable - supports main claims with minor gaps\n- 2: Poor - main claims lack sufficient support\n- 1: Major issues - not ready for publication\n\n*Guidance: \"Given that this is a short/long paper, is it sufficiently sound and thorough? Does it clearly state scientific claims and provide adequate support for them?\"*\n\n#### 2. **Excitement** (1-5 scale, with half-point increments)\n- 5: Highly exciting - would recommend to others/attend presentation\n- 4: Exciting - would mention to others\n- 3: Interesting - might mention to others\n- 2: Potentially interesting - may resonate with some\n- 1: Not exciting - not relevant to NLP community\n\n*Guidance: \"How exciting is this paper for you?\"*\n\n#### 3. **Overall Assessment/Recommendation** (1-5 scale, with half-point increments)\n- 5: Consider for award\n- 4: Conference acceptance\n- 3: Findings acceptance\n- 2: Resubmit next cycle\n- 1: Do not resubmit\n\n*Guidance: Composite score reflecting soundness, excitement, and other factors like novelty and impact*\n\n### Additional Evaluation Dimensions\n\n#### 4. **Reviewer Confidence** (1-5 scale)\n- 5: Positive evaluation; read carefully, familiar with related work\n- 4: Quite sure; checked important points carefully\n- 3: Pretty sure; good general familiarity but didn't check all details\n- 2: Willing to defend evaluation; likely missed some details\n- 1: Outside area or paper very difficult to understand\n\n#### 5. **Reproducibility** (1-5 scale)\n- 5: Results easily reproducible\n- 4: Mostly reproducible with minor variations\n- 3: Reproducible with difficulty\n- 2: Hard to reproduce\n- 1: Cannot reproduce\n\n#### 6. **Datasets & Software** (1-5 scale each)\n- 5: Enabling - affects research project choices\n- 4: Useful - recommended for ongoing work\n- 3: Potentially useful\n- 2: Documentary - useful for replication\n- 1: Not released\n\n#### 7. **Author Identity Knowledge** (1-5 scale)\n- 5: Know author from double-blind violation\n- 4: Know from preprint/workshop\n- 3: Know from submission contents\n- 2: Know from informal communication\n- 1: No educated guess\n\n### Key Reviewer Guidelines for 2025-2026\n\n**Critical Requirements:**\n- Soundness scores MUST be justified by the text of the review\n- Read papers twice (skim, then in-depth) to avoid bias\n- Be specific with criticisms rather than vague generalizations\n- Maintain professional, neutral tone (guidelines emphasize \"a good review should be professional and neutral, if not kind\")\n- Distinguish between actual weaknesses and personal preferences\n- Don't request unnecessary experiments beyond what claims require\n\n**Important Policy Note:** Starting in May 2025, ARR adopts enforcement against \"highly irresponsible\" reviewing, including extremely terse reviews, unprofessional tone, and LLM-generated reviews. Violators may have work desk-rejected and be ineligible for resubmission.\n\n### EMNLP 2026 Specifics\n\nEMNLP 2026 submissions will use the ARR system with the same review form dimensions and criteria above. Review deadlines for EMNLP 2026 are July 6, 2026.\n\nSources:\n- [ARR Reviewer Guidelines](http://aclrollingreview.org/reviewerguidelines)\n- [ACL Rolling Review Form](http://aclrollingreview.org/reviewform)\n- [ARR Area Chair Guidelines](http://aclrollingreview.org/acguidelines)\n- [EMNLP 2026 FAQ](https://2026.emnlp.org/faq/)"
      }
    ],
    "totalDurationMs": 26472,
    "totalTokens": 23253,
    "totalToolUseCount": 5,
    "usage": {
      "input_tokens": 340,
      "cache_creation_input_tokens": 2131,
      "cache_read_input_tokens": 19723,
      "output_tokens": 1059,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2131
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 340,
          "output_tokens": 1059,
          "cache_read_input_tokens": 19723,
          "cache_creation_input_tokens": 2131,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2131,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 0,
      "searchCount": 0,
      "bashCount": 0,
      "editFileCount": 0,
      "linesAdded": 0,
      "linesRemoved": 0,
      "otherToolCount": 5
    }
  },
  "sourceToolAssistantUUID": "e8255f1e-0d73-4953-aad1-311487a8d535",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-22T16:55:08.961Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RLpH29Hnr4n4FDp2td1qos`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4714ac20-b4f3-4e09-ac88-9b5b38e5ab43",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "b4727867-394b-42cc-9c54-323c1a4228a8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 20 · 2026-05-22T16:55:08.997Z_

<details><summary>↩ Tool result · `toolu_01RLpH29Hnr4n4FDp2td1qos`</summary>

```text
1	\begin{abstract}
2	Large language models are increasingly used as annotators in computational social science, yet annotation errors propagate into downstream causal estimates in ways that depend on both the confusion matrix structure and the causal DAG topology. We derive bias expressions for seven canonical topologies under $K$-class non-differential misclassification and show that $K {\geq} 3$ introduces a structural possibility of sign reversal absent in the binary case. We prove sign preservation for confounding and collider, and verify it numerically for mediation, M-bias, and front-door; exposure and IV topologies can reverse the treatment effect sign. Under realistic LLM accuracy (diagonal ${\geq}\,0.7$), the sign reversal rate is 2.1\%, exclusively in secondary coefficients---the primary treatment effect never reverses in any of 23 empirical LLM configurations. We introduce Annotation Sensitivity Values (ASVs) revealing a vulnerability spectrum from IV (maximally fragile) to M-bias (immune), and show that matrix-based corrections are provably ineffective for four topologies due to Frisch--Waugh--Lovell invariance. Topology-aware analysis is necessary for valid causal inference with LLM-generated annotations.
3	\end{abstract}
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b4727867-394b-42cc-9c54-323c1a4228a8",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "7812a368-a797-433c-947e-ee66ed40cbf9",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nLarge language models are increasingly used as annotators in computational social science, yet annotation errors propagate into downstream causal estimates in ways that depend on both the confusion matrix structure and the causal DAG topology. We derive bias expressions for seven canonical topologies under $K$-class non-differential misclassification and show that $K {\\geq} 3$ introduces a structural possibility of sign reversal absent in the binary case. We prove sign preservation for confounding and collider, and verify it numerically for mediation, M-bias, and front-door; exposure and IV topologies can reverse the treatment effect sign. Under realistic LLM accuracy (diagonal ${\\geq}\\,0.7$), the sign reversal rate is 2.1\\%, exclusively in secondary coefficients---the primary treatment effect never reverses in any of 23 empirical LLM configurations. We introduce Annotation Sensitivity Values (ASVs) revealing a vulnerability spectrum from IV (maximally fragile) to M-bias (immune), and show that matrix-based corrections are provably ineffective for four topologies due to Frisch--Waugh--Lovell invariance. Topology-aware analysis is necessary for valid causal inference with LLM-generated annotations.\n\\end{abstract}\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  },
  "sourceToolAssistantUUID": "b4727867-394b-42cc-9c54-323c1a4228a8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-22T16:55:09.441Z_

<details open><summary>🔧 Tool call — Read · `toolu_016eNwWiHyEHu7U7tnA6FAyF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7812a368-a797-433c-947e-ee66ed40cbf9",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "afe432a6-fc0b-40a5-a7f7-300f5520ac82",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 22 · 2026-05-22T16:55:09.459Z_

<details><summary>↩ Tool result · `toolu_016eNwWiHyEHu7U7tnA6FAyF`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Large language models are rapidly replacing human annotators in computational social science, with researchers using LLM-generated labels for tasks ranging from sentiment classification to political stance detection~\cite{gilardi2023chatgpt, ziems2024can, egami_hinck_stewart_wei2023, baumann2025}. Crucially, most of these tasks are inherently multi-class: stance detection uses 3--4 categories, sentiment analysis 5, and disaster response taxonomies 10 or more. This shift promises dramatic cost reduction, but introduces a critical validity gap: annotation errors from imperfect classifiers propagate into downstream causal estimates in ways that depend on both the error structure and the causal design. \citet{baumann2025} demonstrate that across 37 annotation tasks, 31\% of hypotheses yield incorrect conclusions with state-of-the-art LLMs, rising to 50\% for smaller models; these errors are highly correlated across models (60\% agreement when both err)~\cite{kim_garg2025}, undermining ensemble-based mitigation. Analyzing the \emph{structure} of annotation error, rather than simply reducing its magnitude, is essential for valid downstream inference.
5	
6	The transition at $K{\geq}3$ is not gradual but structural. For $K{=}2$, the stochastic constraint forces any confusion matrix with $C_{kk} {>} 0.5$ to preserve coefficient signs---an algebraic property of the $2{\times}2$ matrix dimension, not of a specific error rate~\cite{brenner1993}. This guarantee \emph{vanishes} at $K{\geq}3$: the higher-dimensional confusion matrix admits negative effective weights on categories with opposite-sign coefficients, enabling sign reversal even when every diagonal entry exceeds $0.5$~\cite{veirod_laake2001}. This structural break is quantifiable: under a uniform Dirichlet$(1,1,1)$ prior spanning the full parameter space, 83.4\% of $K{=}3$ exposure confusion matrices produce sign reversal of at least one secondary coefficient (0\% at $K{=}2$); under realistic accuracy (diagonal $\geq 0.7$), 2.1\% do so. Critically, the primary treatment coefficient is never reversed---a structural property we prove in Section~\ref{sec:method}.
7	
8	Standard classification metrics do not predict downstream causal risk: within a narrow $F_1$ range of 0.614--0.690 across three frontier LLMs, relative bias varies by an order of magnitude across topologies (from 4.1\% to 42.1\%), illustrating that \emph{topology}, not annotator quality, determines downstream risk. This fundamental asymmetry has received limited systematic treatment. \citet{dosemeci1990} and \citet{veirod_laake2001} noted the possibility of polytomous sign reversal; \citet{brenner1993} identified amplification for polytomous confounders; \citet{lee_wood_doughty2024} extended classifier error analysis to categorical variables and LLM classifiers, but covered only one DAG topology. No prior work systematically characterizes how the \emph{same} confusion matrix produces qualitatively different bias across causal designs.
9	
10	We address these gaps with three contributions:
11	
12	\begin{enumerate}
13	\item \textbf{Multi-class bias taxonomy.} We derive bias expressions for seven canonical DAG topologies (Figure~\ref{fig:dag_taxonomy}) under $K$-class non-differential misclassification, prove sign preservation for confounding and collider, verify it numerically for mediation, M-bias, and front-door, and show that exposure and IV can produce sign reversal. Binarization amplifies the gap: collapsing $K{=}3$ to binary introduces additional bias varying 154$\times$ across topologies.
14	
15	\item \textbf{Topology-aware correction guidance.} We evaluate five correction methods and prove a Frisch--Waugh--Lovell invariance result: matrix-based corrections achieve exactly 0\% bias reduction for four topologies where $A$ enters as a covariate---a negative result overlooked in the annotation correction literature. PPI++ achieves 47.0\% RMSE reduction but requires gold labels and is harmful for M-bias ($-$88\%).
16	
17	\item \textbf{Annotation Sensitivity Values.} As a corollary of the bias taxonomy, we define three complementary ASV types---magnitude, significance, and sign-flip---revealing a topology-dependent vulnerability spectrum from IV (maximally fragile, 52.6\% sign reversal) to M-bias (immune, ASV $= \infty$).
18	\end{enumerate}
19	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "afe432a6-fc0b-40a5-a7f7-300f5520ac82",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "e9c3bbeb-ff5e-42a3-8fbd-6fd068706cf2",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nLarge language models are rapidly replacing human annotators in computational social science, with researchers using LLM-generated labels for tasks ranging from sentiment classification to political stance detection~\\cite{gilardi2023chatgpt, ziems2024can, egami_hinck_stewart_wei2023, baumann2025}. Crucially, most of these tasks are inherently multi-class: stance detection uses 3--4 categories, sentiment analysis 5, and disaster response taxonomies 10 or more. This shift promises dramatic cost reduction, but introduces a critical validity gap: annotation errors from imperfect classifiers propagate into downstream causal estimates in ways that depend on both the error structure and the causal design. \\citet{baumann2025} demonstrate that across 37 annotation tasks, 31\\% of hypotheses yield incorrect conclusions with state-of-the-art LLMs, rising to 50\\% for smaller models; these errors are highly correlated across models (60\\% agreement when both err)~\\cite{kim_garg2025}, undermining ensemble-based mitigation. Analyzing the \\emph{structure} of annotation error, rather than simply reducing its magnitude, is essential for valid downstream inference.\n\nThe transition at $K{\\geq}3$ is not gradual but structural. For $K{=}2$, the stochastic constraint forces any confusion matrix with $C_{kk} {>} 0.5$ to preserve coefficient signs---an algebraic property of the $2{\\times}2$ matrix dimension, not of a specific error rate~\\cite{brenner1993}. This guarantee \\emph{vanishes} at $K{\\geq}3$: the higher-dimensional confusion matrix admits negative effective weights on categories with opposite-sign coefficients, enabling sign reversal even when every diagonal entry exceeds $0.5$~\\cite{veirod_laake2001}. This structural break is quantifiable: under a uniform Dirichlet$(1,1,1)$ prior spanning the full parameter space, 83.4\\% of $K{=}3$ exposure confusion matrices produce sign reversal of at least one secondary coefficient (0\\% at $K{=}2$); under realistic accuracy (diagonal $\\geq 0.7$), 2.1\\% do so. Critically, the primary treatment coefficient is never reversed---a structural property we prove in Section~\\ref{sec:method}.\n\nStandard classification metrics do not predict downstream causal risk: within a narrow $F_1$ range of 0.614--0.690 across three frontier LLMs, relative bias varies by an order of magnitude across topologies (from 4.1\\% to 42.1\\%), illustrating that \\emph{topology}, not annotator quality, determines downstream risk. This fundamental asymmetry has received limited systematic treatment. \\citet{dosemeci1990} and \\citet{veirod_laake2001} noted the possibility of polytomous sign reversal; \\citet{brenner1993} identified amplification for polytomous confounders; \\citet{lee_wood_doughty2024} extended classifier error analysis to categorical variables and LLM classifiers, but covered only one DAG topology. No prior work systematically characterizes how the \\emph{same} confusion matrix produces qualitatively different bias across causal designs.\n\nWe address these gaps with three contributions:\n\n\\begin{enumerate}\n\\item \\textbf{Multi-class bias taxonomy.} We derive bias expressions for seven canonical DAG topologies (Figure~\\ref{fig:dag_taxonomy}) under $K$-class non-differential misclassification, prove sign preservation for confounding and collider, verify it numerically for mediation, M-bias, and front-door, and show that exposure and IV can produce sign reversal. Binarization amplifies the gap: collapsing $K{=}3$ to binary introduces additional bias varying 154$\\times$ across topologies.\n\n\\item \\textbf{Topology-aware correction guidance.} We evaluate five correction methods and prove a Frisch--Waugh--Lovell invariance result: matrix-based corrections achieve exactly 0\\% bias reduction for four topologies where $A$ enters as a covariate---a negative result overlooked in the annotation correction literature. PPI++ achieves 47.0\\% RMSE reduction but requires gold labels and is harmful for M-bias ($-$88\\%).\n\n\\item \\textbf{Annotation Sensitivity Values.} As a corollary of the bias taxonomy, we define three complementary ASV types---magnitude, significance, and sign-flip---revealing a topology-dependent vulnerability spectrum from IV (maximally fragile, 52.6\\% sign reversal) to M-bias (immune, ASV $= \\infty$).\n\\end{enumerate}\n",
      "numLines": 19,
      "startLine": 1,
      "totalLines": 19
    }
  },
  "sourceToolAssistantUUID": "afe432a6-fc0b-40a5-a7f7-300f5520ac82",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-22T16:55:09.912Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KLAv5iXK5wENH4Ffzi8UZG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e9c3bbeb-ff5e-42a3-8fbd-6fd068706cf2",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "7f21a5b1-cd35-48fe-baf2-9be9c8922e6a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 24 · 2026-05-22T16:55:09.970Z_

<details><summary>↩ Tool result · `toolu_01KLAv5iXK5wENH4Ffzi8UZG`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Measurement error in causal inference.}
5	The foundations are established in \citet{carroll2006}, \citet{gustafson2004}, \citet{buonaccorsi2010}, and \citet{bound2001measurement}, with starred-node DAGs formalized by \citet{hernan_cole2009}. For binary variables, non-differential misclassification biases toward the null~\cite{brenner1993, ogburn_vanderweele2012}, but this fails for polytomous exposures~\cite{dosemeci1990, jurek2005, veirod_laake2001}. \citet{edwards_lessler_naimi2021} showed dependent misclassification can bias in either direction, a concern that also drives mediation analyses with mismeasured mediators~\cite{valeri_vanderweele2013}. All analyze a single DAG topology; ours is the first to characterize how the \emph{same} confusion matrix produces qualitatively different bias across seven topologies.
6	
7	\paragraph{Text classifiers and LLM annotation.}
8	\citet{grimmer2022} and \citet{feder_etal2022} provide foundations for text-as-data and causal inference in NLP. \citet{wood_doughty2018} first applied DAG reasoning to classifier error; \citet{teblunthuis2024} gave the most complete binary treatment ($K{=}2$, four DAGs); \citet{lee_wood_doughty2024} extended to categorical LLM classifiers but covered only confounding. On annotation quality, \citet{gilardi2023chatgpt} and \citet{ziems2024can} document the rapid adoption of LLM annotators, \citet{baumann2025} found 31\% incorrect conclusions, \citet{pangakis_wolken_fasching2023} demonstrated that automated annotations require task-specific validation, \citet{cheng_mayya_sedoc2024} propose structured approaches to reduce LLM measurement error, and \citet{kim_garg2025} showed 60\% error correlation across models. \citet{audinet2025} benchmark debiasing; \citet{keith_jensen_oconnor2020} survey the broader landscape. These works either restrict to binary labels, cover a single topology, or diagnose quality without connecting it to causal validity.
9	
10	\paragraph{Sensitivity analysis and correction methods.}
11	Our ASV framework draws on E-values~\cite{vanderweele_ding2017}, the robustness value of \citet{cinelli2020making}, and the mediation sensitivity analysis of \citet{imai_keele_yamamoto2010}, but parametrizes annotation error severity rather than omitted variable strength or sequential ignorability violations. The unified measurement-error and missing-data framework of \citet{blackwell_honaker_king2017} similarly motivates treating annotation noise as a first-class object of inference. For correction, PPI++~\cite{angelopoulos2023} and DSL~\cite{egami_hinck_stewart_wei2023} are topology-agnostic; \citet{zrnic_candes2024} extend PPI to gold-free settings, and \citet{gligoric2025} leverage LLM confidence scores. Our contribution reveals that this agnosticism is costly: correction effectiveness is itself topology-dependent, with matrix-based methods provably ineffective for four topologies. Bayesian measurement error models~\cite{richardson1993bayesian, gustafson2004} and EM imputation offer alternatives that bypass FWL invariance.
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7f21a5b1-cd35-48fe-baf2-9be9c8922e6a",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "d2794891-2d2b-4b85-8d05-82620af86d92",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Measurement error in causal inference.}\nThe foundations are established in \\citet{carroll2006}, \\citet{gustafson2004}, \\citet{buonaccorsi2010}, and \\citet{bound2001measurement}, with starred-node DAGs formalized by \\citet{hernan_cole2009}. For binary variables, non-differential misclassification biases toward the null~\\cite{brenner1993, ogburn_vanderweele2012}, but this fails for polytomous exposures~\\cite{dosemeci1990, jurek2005, veirod_laake2001}. \\citet{edwards_lessler_naimi2021} showed dependent misclassification can bias in either direction, a concern that also drives mediation analyses with mismeasured mediators~\\cite{valeri_vanderweele2013}. All analyze a single DAG topology; ours is the first to characterize how the \\emph{same} confusion matrix produces qualitatively different bias across seven topologies.\n\n\\paragraph{Text classifiers and LLM annotation.}\n\\citet{grimmer2022} and \\citet{feder_etal2022} provide foundations for text-as-data and causal inference in NLP. \\citet{wood_doughty2018} first applied DAG reasoning to classifier error; \\citet{teblunthuis2024} gave the most complete binary treatment ($K{=}2$, four DAGs); \\citet{lee_wood_doughty2024} extended to categorical LLM classifiers but covered only confounding. On annotation quality, \\citet{gilardi2023chatgpt} and \\citet{ziems2024can} document the rapid adoption of LLM annotators, \\citet{baumann2025} found 31\\% incorrect conclusions, \\citet{pangakis_wolken_fasching2023} demonstrated that automated annotations require task-specific validation, \\citet{cheng_mayya_sedoc2024} propose structured approaches to reduce LLM measurement error, and \\citet{kim_garg2025} showed 60\\% error correlation across models. \\citet{audinet2025} benchmark debiasing; \\citet{keith_jensen_oconnor2020} survey the broader landscape. These works either restrict to binary labels, cover a single topology, or diagnose quality without connecting it to causal validity.\n\n\\paragraph{Sensitivity analysis and correction methods.}\nOur ASV framework draws on E-values~\\cite{vanderweele_ding2017}, the robustness value of \\citet{cinelli2020making}, and the mediation sensitivity analysis of \\citet{imai_keele_yamamoto2010}, but parametrizes annotation error severity rather than omitted variable strength or sequential ignorability violations. The unified measurement-error and missing-data framework of \\citet{blackwell_honaker_king2017} similarly motivates treating annotation noise as a first-class object of inference. For correction, PPI++~\\cite{angelopoulos2023} and DSL~\\cite{egami_hinck_stewart_wei2023} are topology-agnostic; \\citet{zrnic_candes2024} extend PPI to gold-free settings, and \\citet{gligoric2025} leverage LLM confidence scores. Our contribution reveals that this agnosticism is costly: correction effectiveness is itself topology-dependent, with matrix-based methods provably ineffective for four topologies. Bayesian measurement error models~\\cite{richardson1993bayesian, gustafson2004} and EM imputation offer alternatives that bypass FWL invariance.\n",
      "numLines": 12,
      "startLine": 1,
      "totalLines": 12
    }
  },
  "sourceToolAssistantUUID": "7f21a5b1-cd35-48fe-baf2-9be9c8922e6a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-22T16:55:10.384Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AuEkZXHnTyLyd613rzxF3x`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d2794891-2d2b-4b85-8d05-82620af86d92",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "1117f99e-57c5-4aff-9777-ff7e6d2084b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 26 · 2026-05-22T16:55:10.412Z_

<details><summary>↩ Tool result · `toolu_01AuEkZXHnTyLyd613rzxF3x`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Setup and Notation}
5	\label{sec:notation}
6	
7	Let $A$ denote a true $K$-class categorical variable (e.g., sentiment with $K{=}3$ levels) and $A^*$ its observed, potentially misclassified version produced by an LLM annotator. The misclassification process is characterized by a $K{\times}K$ confusion matrix $C$ with entries $C_{jk} = P(A^*{=}j \mid A{=}k)$, where each column sums to one. Following \citet{hernan_cole2009}, we represent this measurement process using \emph{starred-node} DAGs: the true variable $A$ is latent, and the observed $A^*$ is connected to $A$ via a dashed measurement edge.
8	
9	\begin{definition}[Non-differential misclassification]
10	\label{def:nondiff}
11	Misclassification of $A$ is non-differential with respect to outcome $Y$ and covariates $\mathbf{Z}$ if $P(A^*{=}j \mid A{=}k, Y, \mathbf{Z}) = P(A^*{=}j \mid A{=}k) = C_{jk}$ for all $j,k$.
12	\end{definition}
13	
14	This assumption is natural when the LLM annotates treatment labels from source documents without access to outcome information, though it may be violated by outcome-conditional prompting or few-shot demonstrations encoding outcome associations (see Limitations).
15	
16	We study seven canonical DAG topologies (Figure~\ref{fig:dag_taxonomy})~\cite{pearl2009} in which $A$ occupies structurally distinct causal roles: confounder, exposure, mediator, collider, M-bias variable, front-door mediator, and instrument. Each role induces a different functional relationship between $C$ and the probability limit of the standard causal estimator, yielding topology-dependent bias.
17	
18	\subsection{Multi-Class Bias Expressions}
19	\label{sec:bias_expressions}
20	
21	For each topology, we derive the probability limit of the naive estimator that substitutes $A^*$ for $A$. Let $\tau$ denote the target causal parameter and $\hat{\tau}(A^*)$ the estimator using misclassified annotations.
22	
23	\paragraph{Confounding ($A$ = confounder).}
24	When $A$ confounds the $X{\to}Y$ relationship, the OLS estimator controlling for $A^*$ has probability limit
25	\begin{equation}
26	\label{eq:confounding}
27	\text{plim}\;\hat{\tau}(A^*) = \bigl(\mathbb{E}[Z^{\prime}Z]\bigr)^{-1}\mathbb{E}[Z^{\prime}X]\,\boldsymbol{\beta},
28	\end{equation}
29	where $Z = [X, \text{dummies}(A^*)]$, $\boldsymbol{\beta}$ contains the true coefficients, and the target parameter $\tau$ is the coefficient on $X$. Misclassification produces residual confounding that monotonically approaches the omitted variable bias, but the sign of $\hat{\tau}$ is preserved: $\tau_{\text{sign\_flip}} = 0$ structurally.\footnote{This result is consistent with \citet{brenner1993}, who showed that the adjusted estimate with misclassified polytomous confounders can be biased toward or away from the null. Both findings hold simultaneously: misclassification degrades confounding control, producing residual bias whose magnitude can exceed the correctly adjusted estimate (amplification), but the treatment effect sign is never reversed. The distinction is between \emph{sign reversal} ($\text{sign}(\hat{\tau}) \neq \text{sign}(\tau)$, which we show never occurs) and \emph{amplification} ($|\hat{\tau}| > |\tau|$, which occurs universally in this topology).}
30	
31	\paragraph{Exposure ($A$ = treatment variable).}
32	When $A$ is the exposure of interest, the biased coefficient for category $j$ becomes a weighted combination of true coefficients:
33	\begin{equation}
34	\label{eq:exposure}
35	\text{plim}\;\hat{\beta}_j(A^*) = \sum_{k=1}^{K} w_{jk}\,\beta_k,
36	\end{equation}
37	where $w_{jk}$ depends on the confusion matrix $C$ and the marginal distribution of $A$. Unlike the binary case, where non-differential misclassification guarantees attenuation toward the null~\cite{brenner1993}, the $K{\geq}3$ case permits $w_{jk}$ to assign negative weight to categories with opposite-sign coefficients, producing \emph{sign reversal}. A near-permutation confusion matrix effectively swaps category labels, making sign reversal the dominant outcome (83.4\% under uniform Dirichlet prior). This failure mode is structurally impossible at $K{=}2$ because a $2{\times}2$ stochastic matrix with positive diagonal cannot reverse the sign of a single coefficient.
38	
39	\paragraph{Mediation ($A$ = mediator).}
40	When $A$ mediates the $X{\to}Y$ relationship, the direct effect estimator controlling for $A^*$ has probability limit
41	\begin{equation}
42	\label{eq:mediation}
43	\text{plim}\;\hat{\tau}_{\text{direct}}(A^*) = \tau_{\text{direct}} + \bigl(1 - \lambda(C)\bigr)\,\tau_{\text{indirect}},
44	\end{equation}
45	where $\lambda(C) \in [0,1]$ under proportional effects (Appendix~\ref{app:proof}, Proposition~\ref{prop:lambda_bound}), with $\lambda(I) = 1$ under perfect classification. Misclassification ($\lambda < 1$) causes the residual indirect effect to be absorbed into the direct path estimate, producing upward bias in $|\hat{\tau}_{\text{direct}}|$ but preserving the sign ($\tau_{\text{sign\_flip}} = 0$).
46	
47	\paragraph{Collider ($A$ = collider, conditioned on $A^*$).}
48	Conditioning on a collider $A$ of $X$ and $Y$ opens a spurious path. When we condition on $A^*$ instead, misclassification attenuates this spurious association because $A^*$ is a noisy proxy for $A$. The collider topology thus exhibits a \emph{protective} property: annotation error reduces rather than amplifies the bias from collider stratification, with $\tau_{\text{sign\_flip}} = 0$.
49	
50	\paragraph{M-bias ($A$ = intermediate collider).}
51	In the M-shaped DAG ($U_1 \to X$, $U_1 \to A$, $U_2 \to A$, $U_2 \to Y$, $X \to Y$), adjusting for $A$ introduces a small spurious association via the M-bias path~\cite{greenland2003}. Misclassifying $A$ weakens this adjustment, reducing the M-bias. This topology is \emph{immune}: $\hat{\tau}(A^*)$ is closer to $\tau$ than $\hat{\tau}(A)$ for all non-trivial confusion matrices, yielding $\text{ASV} = \infty$.
52	
53	\paragraph{Front-door ($A$ = front-door mediator).}
54	In the front-door DAG ($X \to A \to Y$ with unmeasured $U \to X$, $U \to Y$), the front-door estimator~\cite{bellemare_bloem2024} uses $A$ to identify effects despite unmeasured confounding. Misclassification attenuates both $X \to A$ and $A \to Y$ relationships, producing moderate bias with $\tau_{\text{sign\_flip}} = 0$.
55	
56	\paragraph{Instrumental variable ($A$ = instrument).}
57	The Wald estimator~\cite{angrist_imbens1995} $\hat{\tau}_{\text{IV}} = \hat{\text{cov}}(A^*, Y) / \hat{\text{cov}}(A^*, X)$ has $C$ in the denominator. Misclassification can drive first-stage coefficients toward zero or reverse their sign, causing the ratio estimator to diverge or flip. Under random Dirichlet matrices, 52.6\% produce sign reversal, making IV the most fragile topology.
58	
59	\paragraph{Structural sign-flip guarantee.}
60	\begin{proposition}[Sign preservation---analytic results]
61	\label{prop:signflip}
62	Under non-differential misclassification with $C_{kk} > 0$ for all $k$:
63	\emph{(a)}~Confounding preserves sign when $\operatorname{sign}(\tau) = \operatorname{sign}(\tau {+} B_{\mathrm{OV}})$, where $B_{\mathrm{OV}} {=} \operatorname{Cov}(g(A),f(A))/\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\ref{app:confounding}).
64	\emph{(b)}~Collider preserves sign when $|\tau| > \sqrt{\operatorname{Var}(g)\operatorname{Var}(h)}/\mathbb{E}[\operatorname{Var}(T{\mid}A)]$ (Berkson attenuation; Appendix~\ref{app:collider}).
65	\emph{(c)}~Exposure can produce sign reversal for $K {\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\ref{app:exposure}).
66	\end{proposition}
67	
68	Our theoretical results establish a three-tier hierarchy: (i)~analytically proved (Proposition~\ref{prop:signflip}(a,b), Theorem~\ref{thm:monotone}), (ii)~numerically verified with zero violations across 100{,}000 matrices (mediation, M-bias, front-door sign preservation), and (iii)~conjectured with $\varepsilon$-approximate bounds (Conjecture~\ref{conj:monotone}).
69	
70	\paragraph{Numerical Verification 1} (Mediation, M-bias, front-door).
71	Sign preservation holds under topology-specific conditions: mediation requires $\operatorname{sign}(\tau_{\mathrm{dir}}) {=} \operatorname{sign}(\tau_{\mathrm{total}})$; front-door requires $\operatorname{sign}(\lambda\alpha_U) {=} \operatorname{sign}(\lambda\alpha_U {+} \operatorname{Cov}(T,f(A)))$; M-bias is attenuating for all $C$. Verified across 100{,}000 random matrices with zero violations (Appendix~\ref{app:conditions}); analytic proofs for general $K$ remain open.
72	
73	These conditions involve true DGP parameters, which in practice must be estimated. The ASV framework (§\ref{sec:asv}) provides a complementary assessment that does not require knowledge of the exact sufficient conditions.
74	
75	\subsection{Annotation Sensitivity Values}
76	\label{sec:asv}
77	
78	Our bias taxonomy and FWL invariance results naturally motivate a practical question: how much annotation error can a study tolerate before conclusions change? We define Annotation Sensitivity Values (ASVs) for this purpose, drawing on the E-value framework~\cite{vanderweele_ding2017} but with three key differences: (1)~E-values parametrize a scalar $\Gamma$ that is naturally monotone; ASVs map a $K{\times}K$ matrix to a 1D path $C(\delta)$, requiring proof of $\varepsilon$-approximate monotonicity (Theorem~\ref{thm:monotone}); (2)~three ASV types (magnitude, significance, sign-flip) address topology-dependent failure modes; and (3)~ASVs combine with FWL invariance to route practitioners to topology-appropriate corrections.
79	
80	\paragraph{Parameterization.}
81	We parameterize the confusion matrix as $C(\delta) = (1{-}\delta)I + \delta C_0$, where $C_0$ is a reference confusion matrix (e.g., estimated from a validation set) and $\delta \geq 0$ controls the severity of misclassification. At $\delta{=}0$, classification is perfect; at $\delta{=}1$, classification matches $C_0$. Non-negativity of $C(\delta)$ requires $\delta \leq \delta_{\max} = \min_j \frac{1}{1 - (C_0)_{jj}}$. Since $(C_0)_{jj} \in [0,1]$, we have $\delta_{\max} \geq 1$ for all valid $C_0$, ensuring the full range $[0,1]$ is always feasible; all ASV computations are constrained to $[0, \delta_{\max}]$.
82	\paragraph{Three ASV types.}
83	We define three complementary measures: (1)~\textbf{Magnitude ASV} $\delta^*_{\text{mag}} = \min\{\delta : |\text{plim}\;\hat{\tau}(C(\delta)) - \tau| > \epsilon\}$---analogous to E-values; (2)~\textbf{Significance ASV} $\delta^*_{\text{sig}} = \min\{\delta : |\text{plim}\;\hat{\tau}(C(\delta))| < z_{\alpha/2} \cdot SE(N)\}$---relevant for attenuating topologies; (3)~\textbf{Sign-flip ASV} $\delta^*_{\text{sf}} = \min\{\delta : \text{sign}(\hat{\tau}) \neq \text{sign}(\tau)\}$---exposure and IV only. The significance ASV depends on $N$ through $SE(N)$, exhibiting a sharp phase transition at a critical $N^*$ below which all rejections are blocked.
84	
85	\begin{theorem}[Envelope monotonicity---confounding and mediation]
86	\label{thm:monotone}
87	For confounding and mediation topologies with proportional effects ($f = \lambda g$ for some scalar $\lambda$) under $C(\delta) = (1{-}\delta)I + \delta C_0$, $|B(C(\delta))|$ is monotonically non-decreasing in $\delta \in [0, \delta_{\max}]$.
88	\end{theorem}
89	
90	\emph{Proof sketch.} Both topologies reduce to $B(C(\delta)) {=} \lambda V_W(\delta)/(V_W(\delta) {+} \sigma^2)$ where $V_W(\delta) {=} \operatorname{Var}(g) {-} V_B(\delta)$, $V_B(\delta) {=} \operatorname{Var}(\mathbb{E}[g{\mid}A^*_\delta])$, and $\sigma^2$ is a topology-specific constant ($\sigma_T^2$ for confounding, $\mathbb{E}[\operatorname{Var}(T{\mid}A)]$ for mediation). Under $C(\delta) = (1{-}\delta)I + \delta C_0$, each conditional expectation $\mathbb{E}[g{\mid}A^*_\delta{=}j]$ is a ratio of linear functions of $\delta$, and $V_B(\delta)$ is a rational function whose derivative is non-positive: for $K{=}2$, $dV_B/d\delta < 0$ by direct differentiation; for general $K$, non-positivity is verified algebraically and numerically with zero violations across 10{,}000 random $C_0$ matrices (Appendix~\ref{app:monotonicity_proof}). Since $V_W = \operatorname{Var}(g) - V_B$ is non-decreasing and $x/(x{+}c)$ is increasing for $c{>}0$, $|B|$ is non-decreasing (full proofs in Appendix~\ref{app:monotonicity_proof} and~\ref{par:med_monotone}).
91	
92	\begin{conjecture}[$\varepsilon$-approximate envelope monotonicity]
93	\label{conj:monotone}
94	For non-IV topologies under $C(\delta) = (1{-}\delta)I + \delta C_0$: collider and M-bias (protective topologies) are $\varepsilon$-approximately non-increasing in $\delta$, with $\varepsilon < 0.03$ across all tested $\tau$. Front-door is $\varepsilon$-approximately non-decreasing, with $\varepsilon < 0.06$ for $\tau \leq 2.0$; at extreme $\tau$, normalization artifacts can increase $\varepsilon$ to ${\approx}\,0.14$ (Appendix~\ref{sec:conjecture_verify}). For exposure, $\varepsilon < 0.008$ at the 99th percentile, though extreme-tail matrices ($<$0.02\% of Dirichlet draws) can reach $\varepsilon \approx 0.15$. Mediation envelope monotonicity is proved for proportional effects (Theorem~\ref{thm:monotone}) and verified numerically for the general case with $\varepsilon < 0.02$ at default DGP parameters; small-$\tau$ sensitivity is documented in Appendix~\ref{sec:conjecture_verify}. Verified across 30{,}000 random matrices per topology, $K \in \{3,5,7\}$, and $\tau \in \{0.1, 0.5, 1.0, 2.0, 5.0\}$ using analytic probability limits.
95	\end{conjecture}
96	
97	The IV topology is excluded from Conjecture~\ref{conj:monotone}: the Wald estimator exhibits singularities when the first-stage coefficient passes through zero, producing unbounded deviations. Magnitude ASV remains well-defined away from these singularities.
98	
99	When strict monotonicity holds only approximately, the reported $\delta^*$ may differ from the true threshold by at most $\varepsilon/\eta$ in $\delta$-units---negligible at the recommended $\eta = 10\%$ (e.g., $\varepsilon{=}0.03$ yields ${\leq}0.3$ $\delta$-units). Topology rankings are preserved across all tested configurations.
100	
101	Binarization of $K{=}3$ annotations introduces additional topology-dependent bias (Appendix~\ref{app:binarization}).
102	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1117f99e-57c5-4aff-9777-ff7e6d2084b3",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "e3daac34-07af-4879-bc2f-82770a9ae6de",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Setup and Notation}\n\\label{sec:notation}\n\nLet $A$ denote a true $K$-class categorical variable (e.g., sentiment with $K{=}3$ levels) and $A^*$ its observed, potentially misclassified version produced by an LLM annotator. The misclassification process is characterized by a $K{\\times}K$ confusion matrix $C$ with entries $C_{jk} = P(A^*{=}j \\mid A{=}k)$, where each column sums to one. Following \\citet{hernan_cole2009}, we represent this measurement process using \\emph{starred-node} DAGs: the true variable $A$ is latent, and the observed $A^*$ is connected to $A$ via a dashed measurement edge.\n\n\\begin{definition}[Non-differential misclassification]\n\\label{def:nondiff}\nMisclassification of $A$ is non-differential with respect to outcome $Y$ and covariates $\\mathbf{Z}$ if $P(A^*{=}j \\mid A{=}k, Y, \\mathbf{Z}) = P(A^*{=}j \\mid A{=}k) = C_{jk}$ for all $j,k$.\n\\end{definition}\n\nThis assumption is natural when the LLM annotates treatment labels from source documents without access to outcome information, though it may be violated by outcome-conditional prompting or few-shot demonstrations encoding outcome associations (see Limitations).\n\nWe study seven canonical DAG topologies (Figure~\\ref{fig:dag_taxonomy})~\\cite{pearl2009} in which $A$ occupies structurally distinct causal roles: confounder, exposure, mediator, collider, M-bias variable, front-door mediator, and instrument. Each role induces a different functional relationship between $C$ and the probability limit of the standard causal estimator, yielding topology-dependent bias.\n\n\\subsection{Multi-Class Bias Expressions}\n\\label{sec:bias_expressions}\n\nFor each topology, we derive the probability limit of the naive estimator that substitutes $A^*$ for $A$. Let $\\tau$ denote the target causal parameter and $\\hat{\\tau}(A^*)$ the estimator using misclassified annotations.\n\n\\paragraph{Confounding ($A$ = confounder).}\nWhen $A$ confounds the $X{\\to}Y$ relationship, the OLS estimator controlling for $A^*$ has probability limit\n\\begin{equation}\n\\label{eq:confounding}\n\\text{plim}\\;\\hat{\\tau}(A^*) = \\bigl(\\mathbb{E}[Z^{\\prime}Z]\\bigr)^{-1}\\mathbb{E}[Z^{\\prime}X]\\,\\boldsymbol{\\beta},\n\\end{equation}\nwhere $Z = [X, \\text{dummies}(A^*)]$, $\\boldsymbol{\\beta}$ contains the true coefficients, and the target parameter $\\tau$ is the coefficient on $X$. Misclassification produces residual confounding that monotonically approaches the omitted variable bias, but the sign of $\\hat{\\tau}$ is preserved: $\\tau_{\\text{sign\\_flip}} = 0$ structurally.\\footnote{This result is consistent with \\citet{brenner1993}, who showed that the adjusted estimate with misclassified polytomous confounders can be biased toward or away from the null. Both findings hold simultaneously: misclassification degrades confounding control, producing residual bias whose magnitude can exceed the correctly adjusted estimate (amplification), but the treatment effect sign is never reversed. The distinction is between \\emph{sign reversal} ($\\text{sign}(\\hat{\\tau}) \\neq \\text{sign}(\\tau)$, which we show never occurs) and \\emph{amplification} ($|\\hat{\\tau}| > |\\tau|$, which occurs universally in this topology).}\n\n\\paragraph{Exposure ($A$ = treatment variable).}\nWhen $A$ is the exposure of interest, the biased coefficient for category $j$ becomes a weighted combination of true coefficients:\n\\begin{equation}\n\\label{eq:exposure}\n\\text{plim}\\;\\hat{\\beta}_j(A^*) = \\sum_{k=1}^{K} w_{jk}\\,\\beta_k,\n\\end{equation}\nwhere $w_{jk}$ depends on the confusion matrix $C$ and the marginal distribution of $A$. Unlike the binary case, where non-differential misclassification guarantees attenuation toward the null~\\cite{brenner1993}, the $K{\\geq}3$ case permits $w_{jk}$ to assign negative weight to categories with opposite-sign coefficients, producing \\emph{sign reversal}. A near-permutation confusion matrix effectively swaps category labels, making sign reversal the dominant outcome (83.4\\% under uniform Dirichlet prior). This failure mode is structurally impossible at $K{=}2$ because a $2{\\times}2$ stochastic matrix with positive diagonal cannot reverse the sign of a single coefficient.\n\n\\paragraph{Mediation ($A$ = mediator).}\nWhen $A$ mediates the $X{\\to}Y$ relationship, the direct effect estimator controlling for $A^*$ has probability limit\n\\begin{equation}\n\\label{eq:mediation}\n\\text{plim}\\;\\hat{\\tau}_{\\text{direct}}(A^*) = \\tau_{\\text{direct}} + \\bigl(1 - \\lambda(C)\\bigr)\\,\\tau_{\\text{indirect}},\n\\end{equation}\nwhere $\\lambda(C) \\in [0,1]$ under proportional effects (Appendix~\\ref{app:proof}, Proposition~\\ref{prop:lambda_bound}), with $\\lambda(I) = 1$ under perfect classification. Misclassification ($\\lambda < 1$) causes the residual indirect effect to be absorbed into the direct path estimate, producing upward bias in $|\\hat{\\tau}_{\\text{direct}}|$ but preserving the sign ($\\tau_{\\text{sign\\_flip}} = 0$).\n\n\\paragraph{Collider ($A$ = collider, conditioned on $A^*$).}\nConditioning on a collider $A$ of $X$ and $Y$ opens a spurious path. When we condition on $A^*$ instead, misclassification attenuates this spurious association because $A^*$ is a noisy proxy for $A$. The collider topology thus exhibits a \\emph{protective} property: annotation error reduces rather than amplifies the bias from collider stratification, with $\\tau_{\\text{sign\\_flip}} = 0$.\n\n\\paragraph{M-bias ($A$ = intermediate collider).}\nIn the M-shaped DAG ($U_1 \\to X$, $U_1 \\to A$, $U_2 \\to A$, $U_2 \\to Y$, $X \\to Y$), adjusting for $A$ introduces a small spurious association via the M-bias path~\\cite{greenland2003}. Misclassifying $A$ weakens this adjustment, reducing the M-bias. This topology is \\emph{immune}: $\\hat{\\tau}(A^*)$ is closer to $\\tau$ than $\\hat{\\tau}(A)$ for all non-trivial confusion matrices, yielding $\\text{ASV} = \\infty$.\n\n\\paragraph{Front-door ($A$ = front-door mediator).}\nIn the front-door DAG ($X \\to A \\to Y$ with unmeasured $U \\to X$, $U \\to Y$), the front-door estimator~\\cite{bellemare_bloem2024} uses $A$ to identify effects despite unmeasured confounding. Misclassification attenuates both $X \\to A$ and $A \\to Y$ relationships, producing moderate bias with $\\tau_{\\text{sign\\_flip}} = 0$.\n\n\\paragraph{Instrumental variable ($A$ = instrument).}\nThe Wald estimator~\\cite{angrist_imbens1995} $\\hat{\\tau}_{\\text{IV}} = \\hat{\\text{cov}}(A^*, Y) / \\hat{\\text{cov}}(A^*, X)$ has $C$ in the denominator. Misclassification can drive first-stage coefficients toward zero or reverse their sign, causing the ratio estimator to diverge or flip. Under random Dirichlet matrices, 52.6\\% produce sign reversal, making IV the most fragile topology.\n\n\\paragraph{Structural sign-flip guarantee.}\n\\begin{proposition}[Sign preservation---analytic results]\n\\label{prop:signflip}\nUnder non-differential misclassification with $C_{kk} > 0$ for all $k$:\n\\emph{(a)}~Confounding preserves sign when $\\operatorname{sign}(\\tau) = \\operatorname{sign}(\\tau {+} B_{\\mathrm{OV}})$, where $B_{\\mathrm{OV}} {=} \\operatorname{Cov}(g(A),f(A))/\\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\\ref{app:confounding}).\n\\emph{(b)}~Collider preserves sign when $|\\tau| > \\sqrt{\\operatorname{Var}(g)\\operatorname{Var}(h)}/\\mathbb{E}[\\operatorname{Var}(T{\\mid}A)]$ (Berkson attenuation; Appendix~\\ref{app:collider}).\n\\emph{(c)}~Exposure can produce sign reversal for $K {\\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\\ref{app:exposure}).\n\\end{proposition}\n\nOur theoretical results establish a three-tier hierarchy: (i)~analytically proved (Proposition~\\ref{prop:signflip}(a,b), Theorem~\\ref{thm:monotone}), (ii)~numerically verified with zero violations across 100{,}000 matrices (mediation, M-bias, front-door sign preservation), and (iii)~conjectured with $\\varepsilon$-approximate bounds (Conjecture~\\ref{conj:monotone}).\n\n\\paragraph{Numerical Verification 1} (Mediation, M-bias, front-door).\nSign preservation holds under topology-specific conditions: mediation requires $\\operatorname{sign}(\\tau_{\\mathrm{dir}}) {=} \\operatorname{sign}(\\tau_{\\mathrm{total}})$; front-door requires $\\operatorname{sign}(\\lambda\\alpha_U) {=} \\operatorname{sign}(\\lambda\\alpha_U {+} \\operatorname{Cov}(T,f(A)))$; M-bias is attenuating for all $C$. Verified across 100{,}000 random matrices with zero violations (Appendix~\\ref{app:conditions}); analytic proofs for general $K$ remain open.\n\nThese conditions involve true DGP parameters, which in practice must be estimated. The ASV framework (§\\ref{sec:asv}) provides a complementary assessment that does not require knowledge of the exact sufficient conditions.\n\n\\subsection{Annotation Sensitivity Values}\n\\label{sec:asv}\n\nOur bias taxonomy and FWL invariance results naturally motivate a practical question: how much annotation error can a study tolerate before conclusions change? We define Annotation Sensitivity Values (ASVs) for this purpose, drawing on the E-value framework~\\cite{vanderweele_ding2017} but with three key differences: (1)~E-values parametrize a scalar $\\Gamma$ that is naturally monotone; ASVs map a $K{\\times}K$ matrix to a 1D path $C(\\delta)$, requiring proof of $\\varepsilon$-approximate monotonicity (Theorem~\\ref{thm:monotone}); (2)~three ASV types (magnitude, significance, sign-flip) address topology-dependent failure modes; and (3)~ASVs combine with FWL invariance to route practitioners to topology-appropriate corrections.\n\n\\paragraph{Parameterization.}\nWe parameterize the confusion matrix as $C(\\delta) = (1{-}\\delta)I + \\delta C_0$, where $C_0$ is a reference confusion matrix (e.g., estimated from a validation set) and $\\delta \\geq 0$ controls the severity of misclassification. At $\\delta{=}0$, classification is perfect; at $\\delta{=}1$, classification matches $C_0$. Non-negativity of $C(\\delta)$ requires $\\delta \\leq \\delta_{\\max} = \\min_j \\frac{1}{1 - (C_0)_{jj}}$. Since $(C_0)_{jj} \\in [0,1]$, we have $\\delta_{\\max} \\geq 1$ for all valid $C_0$, ensuring the full range $[0,1]$ is always feasible; all ASV computations are constrained to $[0, \\delta_{\\max}]$.\n\\paragraph{Three ASV types.}\nWe define three complementary measures: (1)~\\textbf{Magnitude ASV} $\\delta^*_{\\text{mag}} = \\min\\{\\delta : |\\text{plim}\\;\\hat{\\tau}(C(\\delta)) - \\tau| > \\epsilon\\}$---analogous to E-values; (2)~\\textbf{Significance ASV} $\\delta^*_{\\text{sig}} = \\min\\{\\delta : |\\text{plim}\\;\\hat{\\tau}(C(\\delta))| < z_{\\alpha/2} \\cdot SE(N)\\}$---relevant for attenuating topologies; (3)~\\textbf{Sign-flip ASV} $\\delta^*_{\\text{sf}} = \\min\\{\\delta : \\text{sign}(\\hat{\\tau}) \\neq \\text{sign}(\\tau)\\}$---exposure and IV only. The significance ASV depends on $N$ through $SE(N)$, exhibiting a sharp phase transition at a critical $N^*$ below which all rejections are blocked.\n\n\\begin{theorem}[Envelope monotonicity---confounding and mediation]\n\\label{thm:monotone}\nFor confounding and mediation topologies with proportional effects ($f = \\lambda g$ for some scalar $\\lambda$) under $C(\\delta) = (1{-}\\delta)I + \\delta C_0$, $|B(C(\\delta))|$ is monotonically non-decreasing in $\\delta \\in [0, \\delta_{\\max}]$.\n\\end{theorem}\n\n\\emph{Proof sketch.} Both topologies reduce to $B(C(\\delta)) {=} \\lambda V_W(\\delta)/(V_W(\\delta) {+} \\sigma^2)$ where $V_W(\\delta) {=} \\operatorname{Var}(g) {-} V_B(\\delta)$, $V_B(\\delta) {=} \\operatorname{Var}(\\mathbb{E}[g{\\mid}A^*_\\delta])$, and $\\sigma^2$ is a topology-specific constant ($\\sigma_T^2$ for confounding, $\\mathbb{E}[\\operatorname{Var}(T{\\mid}A)]$ for mediation). Under $C(\\delta) = (1{-}\\delta)I + \\delta C_0$, each conditional expectation $\\mathbb{E}[g{\\mid}A^*_\\delta{=}j]$ is a ratio of linear functions of $\\delta$, and $V_B(\\delta)$ is a rational function whose derivative is non-positive: for $K{=}2$, $dV_B/d\\delta < 0$ by direct differentiation; for general $K$, non-positivity is verified algebraically and numerically with zero violations across 10{,}000 random $C_0$ matrices (Appendix~\\ref{app:monotonicity_proof}). Since $V_W = \\operatorname{Var}(g) - V_B$ is non-decreasing and $x/(x{+}c)$ is increasing for $c{>}0$, $|B|$ is non-decreasing (full proofs in Appendix~\\ref{app:monotonicity_proof} and~\\ref{par:med_monotone}).\n\n\\begin{conjecture}[$\\varepsilon$-approximate envelope monotonicity]\n\\label{conj:monotone}\nFor non-IV topologies under $C(\\delta) = (1{-}\\delta)I + \\delta C_0$: collider and M-bias (protective topologies) are $\\varepsilon$-approximately non-increasing in $\\delta$, with $\\varepsilon < 0.03$ across all tested $\\tau$. Front-door is $\\varepsilon$-approximately non-decreasing, with $\\varepsilon < 0.06$ for $\\tau \\leq 2.0$; at extreme $\\tau$, normalization artifacts can increase $\\varepsilon$ to ${\\approx}\\,0.14$ (Appendix~\\ref{sec:conjecture_verify}). For exposure, $\\varepsilon < 0.008$ at the 99th percentile, though extreme-tail matrices ($<$0.02\\% of Dirichlet draws) can reach $\\varepsilon \\approx 0.15$. Mediation envelope monotonicity is proved for proportional effects (Theorem~\\ref{thm:monotone}) and verified numerically for the general case with $\\varepsilon < 0.02$ at default DGP parameters; small-$\\tau$ sensitivity is documented in Appendix~\\ref{sec:conjecture_verify}. Verified across 30{,}000 random matrices per topology, $K \\in \\{3,5,7\\}$, and $\\tau \\in \\{0.1, 0.5, 1.0, 2.0, 5.0\\}$ using analytic probability limits.\n\\end{conjecture}\n\nThe IV topology is excluded from Conjecture~\\ref{conj:monotone}: the Wald estimator exhibits singularities when the first-stage coefficient passes through zero, producing unbounded deviations. Magnitude ASV remains well-defined away from these singularities.\n\nWhen strict monotonicity holds only approximately, the reported $\\delta^*$ may differ from the true threshold by at most $\\varepsilon/\\eta$ in $\\delta$-units---negligible at the recommended $\\eta = 10\\%$ (e.g., $\\varepsilon{=}0.03$ yields ${\\leq}0.3$ $\\delta$-units). Topology rankings are preserved across all tested configurations.\n\nBinarization of $K{=}3$ annotations introduces additional topology-dependent bias (Appendix~\\ref{app:binarization}).\n",
      "numLines": 102,
      "startLine": 1,
      "totalLines": 102
    }
  },
  "sourceToolAssistantUUID": "1117f99e-57c5-4aff-9777-ff7e6d2084b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-22T16:55:10.852Z_

<details open><summary>🔧 Tool call — Read · `toolu_01U9cXCaiafY73JCmwH5w1pp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e3daac34-07af-4879-bc2f-82770a9ae6de",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "64f2ef22-c2a7-4061-a610-5190a5360d6d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 28 · 2026-05-22T16:55:10.870Z_

<details><summary>↩ Tool result · `toolu_01U9cXCaiafY73JCmwH5w1pp`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We validate the bias taxonomy and ASV framework through analytical derivations and Monte Carlo simulation across seven DAG topologies under $K{=}3$ non-differential misclassification.
5	
6	\subsection{Setup}
7	\label{sec:setup}
8	
9	For each of the seven topologies (confounding, exposure, mediation, collider, M-bias, front-door, IV), we sample 100{,}000 confusion matrices from a Dirichlet$(1,1,1)$ prior, compute the analytical probability limit of the causal estimator, and validate against Monte Carlo simulation ($N{=}10{,}000$). ASV experiments use $C(\delta) = (1{-}\delta)I + \delta C_0$.
10	
11	\subsection{Bias Taxonomy}
12	\label{sec:taxonomy_results}
13	
14	\paragraph{Theory-MC agreement.}
15	Analytical probability limits match Monte Carlo estimates with grand MAPE of 2.0\% across 126 scenarios (18 LLM configurations $\times$ 7 topologies, $N{=}10{,}000$). Per-topology MAPE ranges from 0.5\% (confounding) to 5.5\% (IV); the IV maximum reflects the Wald estimator's small-denominator variance amplification.
16	
17	\paragraph{Exposure DAG: sign reversal under multi-class misclassification.}
18	Under the full Dirichlet$(1,1,1)$ prior, 85\% of $K{=}3$ confusion matrices produce bias that violates the binary ``toward-null'' guarantee. More critically, 83.4\% of matrices cause \emph{sign reversal} of at least one coefficient. The two failure modes are distinct: for a coefficient with true value $\beta_1{=}1.0$, a near-permutation $C$ produces $\hat{\gamma}_1{=}{-}0.84$ (sign reversal, magnitude $0.84{\times}$); for $\beta_2{=}{-}0.5$, the same $C$ yields $\hat{\gamma}_2{=}{-}1.41$ (same-sign amplification, $2.83{\times}$).
19	
20	This finding persists in practically relevant subspaces. When restricting to confusion matrices with diagonal entries $\geq 0.7$ (typical of current LLM classifiers achieving $F_1 > 0.8$), the violation rate remains 13.7\% with 2.1\% sign reversal and 11.7\% amplification. Even at diagonal $\geq 0.9$, violation persists at 11.9\%. In contrast, the $K{=}2$ control confirms that all six tested binary confusion matrices maintain the classical bias-toward-null guarantee~\cite{brenner1993}, establishing that the multi-class failure is structurally distinct from the binary case.
21	
22	\paragraph{Structural guarantee for non-exposure topologies.}
23	Five of seven topologies exhibit zero sign-flip rate across all sampled matrices (Table~\ref{tab:taxonomy}). Confounding, mediation, and front-door show 100\% violation and amplification but never reverse the sign.\footnote{Consistent with \citet{brenner1993} and \citet{dosemeci1990}: polytomous misclassification can bias \emph{away} from the null (amplification), but our sign-flip metric confirms the effect sign is preserved.} Collider misclassification is protective: conditioning on noisy $A^*$ induces \emph{less} collider bias than conditioning on $A$ ($|B(C)|$ approximately non-increasing; Conjecture~\ref{conj:monotone}). M-bias shows the weakest sensitivity (53.2\% violation, 10.4\% amplification).
24	
25	\paragraph{IV: Wald estimator instability.}
26	The IV topology is the sole non-exposure exception: 52.6\% of random matrices cause the Wald estimator's denominator to change sign. This rate is stable across $K{=}3,5,7$, confirming structural fragility. Unlike exposure, IV violation remains at 100\% even at diagonal $\geq 0.9$ (Appendix~\ref{sec:iv_dirichlet_subspace}).
27	
28	All structural patterns persist at $K{=}5,7$ (Appendix~\ref{sec:cross_k_robustness}).
29	
30	\begin{table}[t]
31	\centering
32	\caption{Bias characteristics of $K{=}3$ non-differential misclassification across 7 DAG topologies. Violation: $|\hat{\tau}| > |\tau|$ (bias exceeds true effect); Sign flip: $\text{sign}(\hat{\tau}) \neq \text{sign}(\tau)$; Amplification: $|\hat{\tau}| > |\tau|$ with same sign; $\tau_{\text{sf}}{=}0$?: structural sign-flip guarantee holds (\checkmark) or not (\ding{55}). Rates over 100{,}000 Dirichlet$(1,1,1)$ random confusion matrices.}
33	\label{tab:taxonomy}
34	\small
35	\begin{tabular}{lcccc}
36	\toprule
37	\textbf{Topology} & \textbf{Violation} & \textbf{Sign Flip} & \textbf{Amplif.} & $\tau_{\text{sf}}{=}0$? \\
38	\midrule
39	Confounding & 100\% & 0\% & 100\% & \checkmark \\
40	Exposure & 85\% & 83.4\% & 14.1\% & \ding{55} \\
41	Mediation & 100\% & 0\% & 100\% & \checkmark \\
42	Front-door & 100\% & 0\% & 100\% & \checkmark \\
43	Collider & 100\% & 0\% & 100\% & \checkmark \\
44	M-bias & 53.2\% & 0\% & 10.4\% & \checkmark \\
45	IV & 100\% & 52.6\% & 100\% & \ding{55} \\
46	\bottomrule
47	\end{tabular}
48	\end{table}
49	
50	The bias distributions are visualized in Figure~\ref{fig:bias_distribution}.
51	
52	\subsection{ASV Framework Validation}
53	\label{sec:asv_results}
54	
55	\paragraph{Envelope monotonicity.}
56	The ASV envelope (bias magnitude as a function of $\delta$) is $\varepsilon$-approximately monotonic for non-IV topologies: collider and M-bias achieve $\varepsilon < 0.03$ across all tested configurations; front-door achieves $\varepsilon < 0.06$ for moderate $\tau$; exposure satisfies $\varepsilon_{p99} < 0.008$ (Conjecture~\ref{conj:monotone}; Appendix~\ref{sec:conjecture_verify}). IV is excluded: the Wald estimator exhibits singularities when the first-stage coefficient passes through zero, producing unbounded deviations. These bounded deviations for non-IV topologies confirm that $\delta$ serves as a meaningful ``dial'' controlling annotation error severity.
57	
58	\paragraph{Magnitude ASV.}
59	Table~\ref{tab:asv_grid} reports magnitude ASV ranges at $\tau{=}0.5$ with a 10\% bias threshold, ranking from most fragile to most robust: front-door (0.064--0.387) $<$ mediation $<$ confounding $<$ IV (0.101--0.607) $<$ collider (0.338--2.028) $<$ M-bias ($\infty$). M-bias achieves infinite ASV because annotation error only reduces the already-small spurious path.
60	
61	\paragraph{Significance and sign-flip ASV.}
62	At $\tau{=}0.05$, significance ASV achieves 100\% power for confounding, front-door, and M-bias, but 0\% for mediation, collider, and IV (correct behavior for attenuating topologies; Type~I error is 0\%). For sign-flip ASV, 83.4\% of exposure reference matrices yield $\tau_{\text{sign\_flip}} < 1$ (extreme sensitivity); IV sign-flip ASV ranges 1.1--6.7 (moderate-to-high). The complete ranking (Figure~\ref{fig:asv_ranking}, Table~\ref{tab:asv_grid}, Appendix~\ref{app:supplementary}) confirms IV as maximally fragile and M-bias as immune (ASV $= \infty$).
63	
64	\paragraph{$N$-sensitivity.}
65	Significance ASV exhibits a sharp phase transition at a critical $N^* \approx 6{,}000$--$10{,}000$ (analytically computable per topology), below which all rejections are blocked. Bootstrap CIs ($B{=}1{,}000$; Appendix~\ref{sec:bootstrap_asv}): $\delta^* = 0.94\,[0.60, 1.36]$ (exposure), $0.75\,[0.44, 1.29]$ (IV).
66	
67	\subsection{Empirical Validation}
68	\label{sec:empirical}
69	
70	We validate using real LLM confusion matrices from three tasks: HumAID~\cite{alam2021humaid} ($K{=}10$), VAST ($K{=}3$), and CivilComments ($K{=}2$). Four LLMs (Llama-4-Maverick, Qwen3-235B, DeepSeek-Chat, Qwen2.5-7B-Instruct) produce 23 configurations across the three datasets under zero-shot and few-shot prompting, yielding 161 bias scenarios ($23 \times 7$ topologies).
71	
72	\paragraph{HumAID ($K{=}10$): theory--practice alignment.}
73	The empirical bias ranking matches predictions: IV (12.4--42.1\%), exposure (9.0--17.4\%), mediation/front-door (10.7--14.8\%), while collider, confounding, and M-bias remain below 10\%---consistent with the ASV vulnerability spectrum.
74	
75	\paragraph{Cross-$K$ comparison.}
76	Bias varies substantially across settings: VAST ($K{=}3$) produces 62.8\% mean bias with IV reaching 326\%, versus 12.2\% for HumAID ($K{=}10$) and 32.4\% for CivilComments ($K{=}2$). Even CivilComments configurations with $F_1{=}0.82$ (Qwen3-235B) produce 62--92\% IV bias, confirming that classification accuracy does not predict downstream causal risk (Figure~\ref{fig:f1_vs_bias}).\footnote{VAST's near-degenerate confusion matrices (Neutral-class recall 3.6--16.1\%) drive its extreme IV bias via the Wald estimator's small-denominator amplification.}
77	
78	Checking all $K{-}1$ exposure coefficients, 14 of 23 configurations (61\%) exhibit sign reversal in at least one coefficient---all in the exposure topology. The primary coefficient ($\beta_1$, largest magnitude) never reverses; sign flips occur exclusively in secondary coefficients with small $|\beta|$ corresponding to rare categories. Sign reversal requires opposite-sign treatment effects across categories (Equation~\ref{eq:exposure}); same-sign $\beta_k$ produce only attenuation. Zero sign reversals occur across 138 non-exposure scenarios ($23 {\times} 6$ topologies), validating the structural guarantee $K$-invariantly.
79	
80	ASV diagnostics flag 55.4\% of HumAID and 100\% of CivilComments scenarios as magnitude-unsafe despite $F_1$ up to 0.82 (Appendix~\ref{sec:asv_diagnostics}). Sign-flip patterns are preserved under logistic DGP ($|\Delta\,\text{SF}_\tau| < 0.02$; Appendix~\ref{sec:logistic_dgp}).
81	
82	\begin{figure}[t]
83	\centering
84	\includegraphics[width=\columnwidth]{fig5_f1_vs_bias.pdf}
85	\caption{Topology determines downstream causal bias, not $F_1$. HumAID $K{=}10$ (56 points): within $F_1$ range 0.614--0.690, bias varies $10{\times}$ (IV 42.1\% vs.\ collider $<$5.6\%).}
86	\label{fig:f1_vs_bias}
87	\end{figure}
88	
89	
90	\subsection{Correction Guidance}
91	\label{sec:correction}
92	
93	We evaluate five correction methods (naive plug-in, MLA, DSL~\cite{egami_hinck_stewart_wei2023}, MC-SIMEX, PPI++~\cite{angelopoulos2023}) across all seven topologies under six error structures (210 configurations; full results in Table~\ref{tab:correction}, Appendix~\ref{app:supplementary}).
94	
95	\paragraph{FWL invariance.}
96	For four topologies where $A$ enters as a covariate (confounding, mediation, collider, M-bias), FWL implies that any linear transformation of the dummy matrix $\mathbf{D}^*$ ($C^{-1}$ premultiplication, MLA, SIMEX) preserves the column space relative to $T$, leaving the treatment coefficient unchanged (Appendix~\ref{app:fwl_proof}). Naive plug-in and MLA achieve exactly 0.0\% bias reduction.
97	
98	\paragraph{Method ranking.}
99	PPI++ achieves the highest grand-mean RMSE reduction (47.0\%) but requires gold labels and is harmful for M-bias ($-$88\%). MC-SIMEX provides gold-free correction (best for IV at 59.4\%) but harms front-door ($-$62.4\%). For protective topologies, correction re-exposes the original bias pathway. No single method dominates: correction effectiveness is itself topology-dependent (Appendix~\ref{app:case_study}).
100	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "64f2ef22-c2a7-4061-a610-5190a5360d6d",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "76247fb4-db4d-49db-ad97-eea6c699a718",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe validate the bias taxonomy and ASV framework through analytical derivations and Monte Carlo simulation across seven DAG topologies under $K{=}3$ non-differential misclassification.\n\n\\subsection{Setup}\n\\label{sec:setup}\n\nFor each of the seven topologies (confounding, exposure, mediation, collider, M-bias, front-door, IV), we sample 100{,}000 confusion matrices from a Dirichlet$(1,1,1)$ prior, compute the analytical probability limit of the causal estimator, and validate against Monte Carlo simulation ($N{=}10{,}000$). ASV experiments use $C(\\delta) = (1{-}\\delta)I + \\delta C_0$.\n\n\\subsection{Bias Taxonomy}\n\\label{sec:taxonomy_results}\n\n\\paragraph{Theory-MC agreement.}\nAnalytical probability limits match Monte Carlo estimates with grand MAPE of 2.0\\% across 126 scenarios (18 LLM configurations $\\times$ 7 topologies, $N{=}10{,}000$). Per-topology MAPE ranges from 0.5\\% (confounding) to 5.5\\% (IV); the IV maximum reflects the Wald estimator's small-denominator variance amplification.\n\n\\paragraph{Exposure DAG: sign reversal under multi-class misclassification.}\nUnder the full Dirichlet$(1,1,1)$ prior, 85\\% of $K{=}3$ confusion matrices produce bias that violates the binary ``toward-null'' guarantee. More critically, 83.4\\% of matrices cause \\emph{sign reversal} of at least one coefficient. The two failure modes are distinct: for a coefficient with true value $\\beta_1{=}1.0$, a near-permutation $C$ produces $\\hat{\\gamma}_1{=}{-}0.84$ (sign reversal, magnitude $0.84{\\times}$); for $\\beta_2{=}{-}0.5$, the same $C$ yields $\\hat{\\gamma}_2{=}{-}1.41$ (same-sign amplification, $2.83{\\times}$).\n\nThis finding persists in practically relevant subspaces. When restricting to confusion matrices with diagonal entries $\\geq 0.7$ (typical of current LLM classifiers achieving $F_1 > 0.8$), the violation rate remains 13.7\\% with 2.1\\% sign reversal and 11.7\\% amplification. Even at diagonal $\\geq 0.9$, violation persists at 11.9\\%. In contrast, the $K{=}2$ control confirms that all six tested binary confusion matrices maintain the classical bias-toward-null guarantee~\\cite{brenner1993}, establishing that the multi-class failure is structurally distinct from the binary case.\n\n\\paragraph{Structural guarantee for non-exposure topologies.}\nFive of seven topologies exhibit zero sign-flip rate across all sampled matrices (Table~\\ref{tab:taxonomy}). Confounding, mediation, and front-door show 100\\% violation and amplification but never reverse the sign.\\footnote{Consistent with \\citet{brenner1993} and \\citet{dosemeci1990}: polytomous misclassification can bias \\emph{away} from the null (amplification), but our sign-flip metric confirms the effect sign is preserved.} Collider misclassification is protective: conditioning on noisy $A^*$ induces \\emph{less} collider bias than conditioning on $A$ ($|B(C)|$ approximately non-increasing; Conjecture~\\ref{conj:monotone}). M-bias shows the weakest sensitivity (53.2\\% violation, 10.4\\% amplification).\n\n\\paragraph{IV: Wald estimator instability.}\nThe IV topology is the sole non-exposure exception: 52.6\\% of random matrices cause the Wald estimator's denominator to change sign. This rate is stable across $K{=}3,5,7$, confirming structural fragility. Unlike exposure, IV violation remains at 100\\% even at diagonal $\\geq 0.9$ (Appendix~\\ref{sec:iv_dirichlet_subspace}).\n\nAll structural patterns persist at $K{=}5,7$ (Appendix~\\ref{sec:cross_k_robustness}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Bias characteristics of $K{=}3$ non-differential misclassification across 7 DAG topologies. Violation: $|\\hat{\\tau}| > |\\tau|$ (bias exceeds true effect); Sign flip: $\\text{sign}(\\hat{\\tau}) \\neq \\text{sign}(\\tau)$; Amplification: $|\\hat{\\tau}| > |\\tau|$ with same sign; $\\tau_{\\text{sf}}{=}0$?: structural sign-flip guarantee holds (\\checkmark) or not (\\ding{55}). Rates over 100{,}000 Dirichlet$(1,1,1)$ random confusion matrices.}\n\\label{tab:taxonomy}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Violation} & \\textbf{Sign Flip} & \\textbf{Amplif.} & $\\tau_{\\text{sf}}{=}0$? \\\\\n\\midrule\nConfounding & 100\\% & 0\\% & 100\\% & \\checkmark \\\\\nExposure & 85\\% & 83.4\\% & 14.1\\% & \\ding{55} \\\\\nMediation & 100\\% & 0\\% & 100\\% & \\checkmark \\\\\nFront-door & 100\\% & 0\\% & 100\\% & \\checkmark \\\\\nCollider & 100\\% & 0\\% & 100\\% & \\checkmark \\\\\nM-bias & 53.2\\% & 0\\% & 10.4\\% & \\checkmark \\\\\nIV & 100\\% & 52.6\\% & 100\\% & \\ding{55} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe bias distributions are visualized in Figure~\\ref{fig:bias_distribution}.\n\n\\subsection{ASV Framework Validation}\n\\label{sec:asv_results}\n\n\\paragraph{Envelope monotonicity.}\nThe ASV envelope (bias magnitude as a function of $\\delta$) is $\\varepsilon$-approximately monotonic for non-IV topologies: collider and M-bias achieve $\\varepsilon < 0.03$ across all tested configurations; front-door achieves $\\varepsilon < 0.06$ for moderate $\\tau$; exposure satisfies $\\varepsilon_{p99} < 0.008$ (Conjecture~\\ref{conj:monotone}; Appendix~\\ref{sec:conjecture_verify}). IV is excluded: the Wald estimator exhibits singularities when the first-stage coefficient passes through zero, producing unbounded deviations. These bounded deviations for non-IV topologies confirm that $\\delta$ serves as a meaningful ``dial'' controlling annotation error severity.\n\n\\paragraph{Magnitude ASV.}\nTable~\\ref{tab:asv_grid} reports magnitude ASV ranges at $\\tau{=}0.5$ with a 10\\% bias threshold, ranking from most fragile to most robust: front-door (0.064--0.387) $<$ mediation $<$ confounding $<$ IV (0.101--0.607) $<$ collider (0.338--2.028) $<$ M-bias ($\\infty$). M-bias achieves infinite ASV because annotation error only reduces the already-small spurious path.\n\n\\paragraph{Significance and sign-flip ASV.}\nAt $\\tau{=}0.05$, significance ASV achieves 100\\% power for confounding, front-door, and M-bias, but 0\\% for mediation, collider, and IV (correct behavior for attenuating topologies; Type~I error is 0\\%). For sign-flip ASV, 83.4\\% of exposure reference matrices yield $\\tau_{\\text{sign\\_flip}} < 1$ (extreme sensitivity); IV sign-flip ASV ranges 1.1--6.7 (moderate-to-high). The complete ranking (Figure~\\ref{fig:asv_ranking}, Table~\\ref{tab:asv_grid}, Appendix~\\ref{app:supplementary}) confirms IV as maximally fragile and M-bias as immune (ASV $= \\infty$).\n\n\\paragraph{$N$-sensitivity.}\nSignificance ASV exhibits a sharp phase transition at a critical $N^* \\approx 6{,}000$--$10{,}000$ (analytically computable per topology), below which all rejections are blocked. Bootstrap CIs ($B{=}1{,}000$; Appendix~\\ref{sec:bootstrap_asv}): $\\delta^* = 0.94\\,[0.60, 1.36]$ (exposure), $0.75\\,[0.44, 1.29]$ (IV).\n\n\\subsection{Empirical Validation}\n\\label{sec:empirical}\n\nWe validate using real LLM confusion matrices from three tasks: HumAID~\\cite{alam2021humaid} ($K{=}10$), VAST ($K{=}3$), and CivilComments ($K{=}2$). Four LLMs (Llama-4-Maverick, Qwen3-235B, DeepSeek-Chat, Qwen2.5-7B-Instruct) produce 23 configurations across the three datasets under zero-shot and few-shot prompting, yielding 161 bias scenarios ($23 \\times 7$ topologies).\n\n\\paragraph{HumAID ($K{=}10$): theory--practice alignment.}\nThe empirical bias ranking matches predictions: IV (12.4--42.1\\%), exposure (9.0--17.4\\%), mediation/front-door (10.7--14.8\\%), while collider, confounding, and M-bias remain below 10\\%---consistent with the ASV vulnerability spectrum.\n\n\\paragraph{Cross-$K$ comparison.}\nBias varies substantially across settings: VAST ($K{=}3$) produces 62.8\\% mean bias with IV reaching 326\\%, versus 12.2\\% for HumAID ($K{=}10$) and 32.4\\% for CivilComments ($K{=}2$). Even CivilComments configurations with $F_1{=}0.82$ (Qwen3-235B) produce 62--92\\% IV bias, confirming that classification accuracy does not predict downstream causal risk (Figure~\\ref{fig:f1_vs_bias}).\\footnote{VAST's near-degenerate confusion matrices (Neutral-class recall 3.6--16.1\\%) drive its extreme IV bias via the Wald estimator's small-denominator amplification.}\n\nChecking all $K{-}1$ exposure coefficients, 14 of 23 configurations (61\\%) exhibit sign reversal in at least one coefficient---all in the exposure topology. The primary coefficient ($\\beta_1$, largest magnitude) never reverses; sign flips occur exclusively in secondary coefficients with small $|\\beta|$ corresponding to rare categories. Sign reversal requires opposite-sign treatment effects across categories (Equation~\\ref{eq:exposure}); same-sign $\\beta_k$ produce only attenuation. Zero sign reversals occur across 138 non-exposure scenarios ($23 {\\times} 6$ topologies), validating the structural guarantee $K$-invariantly.\n\nASV diagnostics flag 55.4\\% of HumAID and 100\\% of CivilComments scenarios as magnitude-unsafe despite $F_1$ up to 0.82 (Appendix~\\ref{sec:asv_diagnostics}). Sign-flip patterns are preserved under logistic DGP ($|\\Delta\\,\\text{SF}_\\tau| < 0.02$; Appendix~\\ref{sec:logistic_dgp}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig5_f1_vs_bias.pdf}\n\\caption{Topology determines downstream causal bias, not $F_1$. HumAID $K{=}10$ (56 points): within $F_1$ range 0.614--0.690, bias varies $10{\\times}$ (IV 42.1\\% vs.\\ collider $<$5.6\\%).}\n\\label{fig:f1_vs_bias}\n\\end{figure}\n\n\n\\subsection{Correction Guidance}\n\\label{sec:correction}\n\nWe evaluate five correction methods (naive plug-in, MLA, DSL~\\cite{egami_hinck_stewart_wei2023}, MC-SIMEX, PPI++~\\cite{angelopoulos2023}) across all seven topologies under six error structures (210 configurations; full results in Table~\\ref{tab:correction}, Appendix~\\ref{app:supplementary}).\n\n\\paragraph{FWL invariance.}\nFor four topologies where $A$ enters as a covariate (confounding, mediation, collider, M-bias), FWL implies that any linear transformation of the dummy matrix $\\mathbf{D}^*$ ($C^{-1}$ premultiplication, MLA, SIMEX) preserves the column space relative to $T$, leaving the treatment coefficient unchanged (Appendix~\\ref{app:fwl_proof}). Naive plug-in and MLA achieve exactly 0.0\\% bias reduction.\n\n\\paragraph{Method ranking.}\nPPI++ achieves the highest grand-mean RMSE reduction (47.0\\%) but requires gold labels and is harmful for M-bias ($-$88\\%). MC-SIMEX provides gold-free correction (best for IV at 59.4\\%) but harms front-door ($-$62.4\\%). For protective topologies, correction re-exposes the original bias pathway. No single method dominates: correction effectiveness is itself topology-dependent (Appendix~\\ref{app:case_study}).\n",
      "numLines": 100,
      "startLine": 1,
      "totalLines": 100
    }
  },
  "sourceToolAssistantUUID": "64f2ef22-c2a7-4061-a610-5190a5360d6d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-22T16:55:11.322Z_

<details open><summary>🔧 Tool call — Read · `toolu_01C8t8izsSYNmw7qr9AVwQay`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "76247fb4-db4d-49db-ad97-eea6c699a718",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "ffb74cfe-8753-458e-ad38-870773f4bb2a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 30 · 2026-05-22T16:55:11.342Z_

<details><summary>↩ Tool result · `toolu_01C8t8izsSYNmw7qr9AVwQay`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We characterized how multi-class annotation errors interact with causal DAG topology across seven canonical topologies. The classical binary guarantee breaks at $K \geq 3$: exposure and IV topologies produce sign reversal, while five topologies maintain a structural guarantee. The ASV framework reveals a vulnerability spectrum from IV (maximally fragile) to M-bias (immune), and matrix-based corrections are provably ineffective for four topologies due to FWL invariance. Empirical validation with 23 real LLM configurations confirms: the primary treatment effect never reverses, but 61\% of exposure configurations reverse a secondary coefficient. Differential misclassification and correlated multi-LLM errors are natural extensions. Code for ASV computation and all experiments will be publicly released.
5	
6	\section*{Limitations}
7	
8	Our framework assumes non-differential misclassification ($P(A^*|A, Y, \mathbf{Z}) = P(A^*|A)$), which holds when the LLM does not observe $Y$ but may be violated when it accesses $Y$-correlated information---e.g., outcome-conditional prompting, few-shot demonstrations encoding outcome--treatment associations, or retrieval-augmented annotation carrying outcome signal (Appendix~\ref{sec:nondiff_stress}). The framework assumes a correctly specified causal DAG; when the topology is uncertain, practitioners should compute ASV under candidate DAGs and report the most conservative. Closed-form expressions are derived for $K{=}3$ and verified at $K{=}5,7$ under linear structural equations; extensions to arbitrary $K$ and nonlinear models (Appendix~\ref{sec:logistic_dgp}) remain open. We address misclassification of $A$ by a single annotator; outcome misclassification and correlated multi-annotator settings~\cite{kim_garg2025} introduce additional bias channels not captured here.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ffb74cfe-8753-458e-ad38-870773f4bb2a",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "4dacc551-b174-41ed-86ee-eeb40ac617bc",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe characterized how multi-class annotation errors interact with causal DAG topology across seven canonical topologies. The classical binary guarantee breaks at $K \\geq 3$: exposure and IV topologies produce sign reversal, while five topologies maintain a structural guarantee. The ASV framework reveals a vulnerability spectrum from IV (maximally fragile) to M-bias (immune), and matrix-based corrections are provably ineffective for four topologies due to FWL invariance. Empirical validation with 23 real LLM configurations confirms: the primary treatment effect never reverses, but 61\\% of exposure configurations reverse a secondary coefficient. Differential misclassification and correlated multi-LLM errors are natural extensions. Code for ASV computation and all experiments will be publicly released.\n\n\\section*{Limitations}\n\nOur framework assumes non-differential misclassification ($P(A^*|A, Y, \\mathbf{Z}) = P(A^*|A)$), which holds when the LLM does not observe $Y$ but may be violated when it accesses $Y$-correlated information---e.g., outcome-conditional prompting, few-shot demonstrations encoding outcome--treatment associations, or retrieval-augmented annotation carrying outcome signal (Appendix~\\ref{sec:nondiff_stress}). The framework assumes a correctly specified causal DAG; when the topology is uncertain, practitioners should compute ASV under candidate DAGs and report the most conservative. Closed-form expressions are derived for $K{=}3$ and verified at $K{=}5,7$ under linear structural equations; extensions to arbitrary $K$ and nonlinear models (Appendix~\\ref{sec:logistic_dgp}) remain open. We address misclassification of $A$ by a single annotator; outcome misclassification and correlated multi-annotator settings~\\cite{kim_garg2025} introduce additional bias channels not captured here.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  },
  "sourceToolAssistantUUID": "ffb74cfe-8753-458e-ad38-870773f4bb2a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-22T16:55:11.892Z_

<details open><summary>🔧 Tool call — Read · `toolu_01L1YG4WTEo5vsSxNcqXFYW8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4dacc551-b174-41ed-86ee-eeb40ac617bc",
  "isSidechain": false,
  "requestId": "req_011CbHxWrCTtaqGrwFyjUkwf",
  "type": "assistant",
  "uuid": "ea9fb950-2897-492c-9309-d08832a3aa1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KPjRTisy5EKwzyMQzg1oon",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 835,
      "cache_creation_input_tokens": 1575,
      "cache_read_input_tokens": 28874,
      "output_tokens": 520,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1575,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 835,
          "output_tokens": 520,
          "cache_read_input_tokens": 28874,
          "cache_creation_input_tokens": 1575,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1575
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

_source line 32_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "ea9fb950-2897-492c-9309-d08832a3aa1a",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Tool result

_source line 33 · 2026-05-22T16:55:12.304Z_

<details><summary>↩ Tool result · reported error · `toolu_01L1YG4WTEo5vsSxNcqXFYW8`</summary>

```text
File content (31027 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ea9fb950-2897-492c-9309-d08832a3aa1a",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "0968dd41-9903-427a-b16b-05c8bb7501e0",
  "toolUseResult": "Error: File content (31027 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "ea9fb950-2897-492c-9309-d08832a3aa1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 34 · 2026-05-22T16:55:12.329Z_

```json
{
  "parentUuid": "0968dd41-9903-427a-b16b-05c8bb7501e0",
  "isSidechain": false,
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "ListMcpResourcesTool",
      "ReadMcpResourceTool",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director"
    ],
    "addedLines": [
      "ListMcpResourcesTool",
      "ReadMcpResourceTool",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "21d7ac93-86c7-4c84-8795-a46b88d58091",
  "timestamp": "2026-05-22T16:55:12.329Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 35 · 2026-05-22T16:55:12.334Z_

```json
{
  "parentUuid": "21d7ac93-86c7-4c84-8795-a46b88d58091",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "6356a168-c632-414c-bbb0-5fa1ba2f0484",
  "timestamp": "2026-05-22T16:55:12.334Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 36 · 2026-05-22T16:55:15.211Z_

<details><summary>Logged reasoning block</summary>

```text
I need to read the appendix in parts since it's too long. Let me read it in sections. I also need to load the tool for posting to director.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6356a168-c632-414c-bbb0-5fa1ba2f0484",
  "isSidechain": false,
  "requestId": "req_011CbHxXNoxomAT9RQrVeqyM",
  "type": "assistant",
  "uuid": "3972e132-b9ae-49f4-a90a-1a55b79e9b58",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NwHn6cF84EpseTEsBq4AwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13201,
      "cache_read_input_tokens": 30449,
      "output_tokens": 279,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13201,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 279,
          "cache_read_input_tokens": 30449,
          "cache_creation_input_tokens": 13201,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13201
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

_source line 37 · 2026-05-22T16:55:15.752Z_

读取 appendix 分段进行。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3972e132-b9ae-49f4-a90a-1a55b79e9b58",
  "isSidechain": false,
  "requestId": "req_011CbHxXNoxomAT9RQrVeqyM",
  "type": "assistant",
  "uuid": "69293995-b5c7-41dd-b81f-bf7067c2e10b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NwHn6cF84EpseTEsBq4AwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13201,
      "cache_read_input_tokens": 30449,
      "output_tokens": 279,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13201,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 279,
          "cache_read_input_tokens": 30449,
          "cache_creation_input_tokens": 13201,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13201
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

_source line 38 · 2026-05-22T16:55:17.781Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JBiJy7UAzRNx23DSq3mrK6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "limit": 400
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "69293995-b5c7-41dd-b81f-bf7067c2e10b",
  "isSidechain": false,
  "requestId": "req_011CbHxXNoxomAT9RQrVeqyM",
  "type": "assistant",
  "uuid": "5c713d1e-235e-43e5-a90e-fe45e90bab1f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NwHn6cF84EpseTEsBq4AwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13201,
      "cache_read_input_tokens": 30449,
      "output_tokens": 279,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13201,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 279,
          "cache_read_input_tokens": 30449,
          "cache_creation_input_tokens": 13201,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13201
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

_source line 39 · 2026-05-22T16:55:17.810Z_

<details><summary>↩ Tool result · `toolu_01JBiJy7UAzRNx23DSq3mrK6`</summary>

```text
1	\section{Proofs of Proposition~\ref{prop:signflip} and Theorem~\ref{thm:monotone}}
2	\label{app:proof}
3	
4	We provide algebraic proofs of sign preservation for the confounding and collider topologies (Proposition~\ref{prop:signflip}(a)--(b)), an explicit counterexample for exposure (Proposition~\ref{prop:signflip}(c)), numerical verification for mediation, M-bias, and front-door (Numerical Verification~1), and the monotonicity proof for confounding (Theorem~\ref{thm:monotone}).
5	Throughout, $A\in\{0,1,\dots,K{-}1\}$ with prior $p_k=P(A{=}k)$, and $C$ is a $K{\times}K$ column-stochastic confusion matrix with $C_{jk}=P(A^*{=}j\mid A{=}k)$.
6	We use category~0 as the reference and let $D_j=\mathbf{1}(A{=}j)$, $D_j^*=\mathbf{1}(A^*{=}j)$ for $j=1,\dots,K{-}1$.
7	
8	\subsection{Notation and Key Identities}
9	\label{app:notation}
10	
11	Under non-differential misclassification, the misclassified moments factor linearly through $C$.
12	Define the population vectors:
13	\begin{align}
14	  q_j &= P(A^*{=}j) = \textstyle\sum_k C_{jk}\,p_k, \label{eq:q}\\
15	  \mathrm{ct}_j &= \mathbb{E}[T\cdot D_j^*] = \textstyle\sum_k C_{jk}\,\mathbb{E}[T\cdot D_k], \label{eq:ct}\\
16	  \mathrm{cy}_j &= \mathbb{E}[Y\cdot D_j^*] = \textstyle\sum_k C_{jk}\,\mathbb{E}[Y\cdot D_k]. \label{eq:cy}
17	\end{align}
18	Write $q = Cp$, $\mathrm{ct} = C\,\mathbb{E}[T\cdot D]$, and $\mathrm{cy} = C\,\mathbb{E}[Y\cdot D]$, where $D=(D_0,\dots,D_{K-1})^\top$.
19	
20	\subsection{Frisch--Waugh--Lovell Decomposition}
21	\label{app:fwl}
22	
23	For topologies where $T$ is directly observed (confounding, mediation, collider, M-bias, front-door), the estimator regresses $Y$ on $Z^*=(1,T,D_1^*,\dots,D_{K-1}^*)$.
24	By the Frisch--Waugh--Lovell (FWL) theorem, the coefficient on $T$ satisfies:
25	\begin{equation}
26	  \operatorname{plim}\hat{\tau}(C)
27	  = \frac{\mathbb{E}[\tilde{T}\,\tilde{Y}]}{\mathbb{E}[\tilde{T}^2]},
28	  \label{eq:fwl}
29	\end{equation}
30	where $\tilde{T}=T-\mathbb{E}[T\mid A^*]$ and $\tilde{Y}=Y-\mathbb{E}[Y\mid A^*]$ are residuals from projecting onto $(1,D_1^*,\dots,D_{K-1}^*)$.
31	
32	\begin{lemma}[Bias decomposition]
33	\label{lem:bias_decomp}
34	Suppose $Y = \tau T + f(A) + \varepsilon_Y$ with $\varepsilon_Y \perp (T, A, A^*)$.
35	Then
36	\begin{equation}
37	  \operatorname{plim}\hat\tau(C) = \tau + \frac{R(C)}{D(C)},
38	  \label{eq:bias_decomp}
39	\end{equation}
40	where
41	\begin{align}
42	  R(C) &= \mathbb{E}\bigl[\operatorname{Cov}(T,\,f(A)\mid A^*)\bigr], \label{eq:R}\\
43	  D(C) &= \mathbb{E}\bigl[\operatorname{Var}(T\mid A^*)\bigr] > 0. \label{eq:D}
44	\end{align}
45	\end{lemma}
46	
47	\begin{proof}
48	Expand $\tilde{Y}$ using $Y=\tau T + f(A) + \varepsilon_Y$:
49	\[
50	  \tilde{Y} = \tau\,\tilde{T} + \bigl(f(A) - \mathbb{E}[f(A)\mid A^*]\bigr) + \varepsilon_Y.
51	\]
52	Since $\tilde{T}$ is measurable w.r.t.\ $(T,A^*)$ and $\varepsilon_Y\perp(T,A,A^*)$:
53	\[
54	  \mathbb{E}[\tilde{T}\,\tilde{Y}]
55	  = \tau\,\mathbb{E}[\tilde{T}^2]
56	  + \mathbb{E}\bigl[\tilde{T}\,\bigl(f(A)-\mathbb{E}[f(A)\mid A^*]\bigr)\bigr].
57	\]
58	The numerator residual is $R(C) = \mathbb{E}[\tilde{T}(f(A)-\mathbb{E}[f(A)\mid A^*])]$, and the denominator is $D(C) = \mathbb{E}[\tilde{T}^2]$.
59	
60	By the law of total covariance:
61	\[
62	  R(C) = \sum_{j=0}^{K-1} q_j\,\operatorname{Cov}(T,\,f(A)\mid A^*{=}j)
63	  = \mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)].
64	\]
65	For $D(C)>0$: decompose $T = g(A) + \varepsilon_T$ where $g(A)=\mathbb{E}[T\mid A]$ (for confounding) or simply note that $T$ has exogenous variation independent of $A^*$ (for mediation).
66	In both cases, $\tilde{T}=\bigl(g(A)-\mathbb{E}[g(A)\mid A^*]\bigr)+\varepsilon_T'$, where $\varepsilon_T'$ is the component of $T$ independent of $(A,A^*)$.
67	Hence $D(C)\geq\operatorname{Var}(\varepsilon_T')>0$.
68	\end{proof}
69	
70	\subsection{Confounding Topology ($A$ = Confounder)}
71	\label{app:confounding}
72	
73	\paragraph{Data-generating process.}
74	$A\to T$, $A\to Y$, $T\to Y$.
75	Using dummy coding with category 0 as reference:
76	\begin{align*}
77	  T &= \sum_{j=1}^{K-1}\alpha_j D_j + \varepsilon_T,\quad
78	  \varepsilon_T\sim\mathcal{N}(0,\sigma_T^2),\;\varepsilon_T\perp A,\\
79	  Y &= \tau\, T + \sum_{j=1}^{K-1}\beta_j^{(A)} D_j + \varepsilon_Y,\quad
80	  \varepsilon_Y\sim\mathcal{N}(0,1),\;\varepsilon_Y\perp(T,A).
81	\end{align*}
82	Define $g(k)=\sum_{j}\alpha_j\mathbf{1}(k{=}j)$ and $f(k)=\sum_{j}\beta_j^{(A)}\mathbf{1}(k{=}j)$, so $g(0)=f(0)=0$.
83	
84	\paragraph{Closed-form plim.}
85	Using the FWL decomposition, the coefficient on $T$ is:
86	\begin{equation}
87	  \operatorname{plim}\hat\tau(C)
88	  = \frac{\mu_{TY} - \sum_{j=0}^{K-1}\frac{\mathrm{ct}_j\,\mathrm{cy}_j}{q_j}}
89	  {s_T - \sum_{j=0}^{K-1}\frac{\mathrm{ct}_j^2}{q_j}},
90	  \label{eq:plim_conf}
91	\end{equation}
92	where $s_T=\mathbb{E}[T^2]$, $\mu_{TY}=\mathbb{E}[TY]$, and $\mathrm{ct}_j$, $\mathrm{cy}_j$, $q_j$ are defined in~\eqref{eq:q}--\eqref{eq:cy}.
93	
94	\begin{proof}[Derivation]
95	By FWL, $\operatorname{plim}\hat\tau = \mathbb{E}[\tilde{T}Y]/\mathbb{E}[\tilde{T}^2]$ where $\tilde{T}=T-\mathbb{E}[T\mid A^*]$.
96	Since $\mathbb{E}[T\mid A^*{=}j]=\mathrm{ct}_j/q_j$:
97	\begin{align*}
98	  \mathbb{E}[\tilde{T}^2]
99	  &= \mathbb{E}[T^2] - \sum_j q_j\bigl(\mathrm{ct}_j/q_j\bigr)^2
100	  = s_T - \sum_j \mathrm{ct}_j^2/q_j,\\
101	  \mathbb{E}[\tilde{T}\,Y]
102	  &= \mathbb{E}[TY] - \sum_j \bigl(\mathrm{ct}_j/q_j\bigr)\,\mathbb{E}[Y\cdot D_j^*]
103	  = \mu_{TY} - \sum_j \mathrm{ct}_j\,\mathrm{cy}_j/q_j.
104	\end{align*}
105	\end{proof}
106	
107	\paragraph{Verification at $C=I$.}
108	When $C=I$: $q_j=p_j$, $\mathrm{ct}_j=\mathbb{E}[T D_j]=\alpha_j p_j$, $\mathrm{cy}_j=\mathbb{E}[Y D_j]=p_j(\tau\alpha_j+\beta_j^{(A)})$.
109	Direct substitution yields numerator $= \tau\sigma_T^2$ and denominator $= \sigma_T^2$, giving $\operatorname{plim}\hat\tau = \tau$.
110	
111	\paragraph{Bias structure.}
112	By Lemma~\ref{lem:bias_decomp}:
113	\begin{equation}
114	  \operatorname{plim}\hat\tau(C) = \tau + B(C),\quad
115	  B(C) = \frac{\mathbb{E}[\operatorname{Cov}(g(A),\,f(A)\mid A^*)]}{D(C)}.
116	  \label{eq:bias_conf}
117	\end{equation}
118	By the law of total covariance:
119	\begin{equation}
120	  \mathbb{E}[\operatorname{Cov}(g,f\mid A^*)]
121	  = \operatorname{Cov}(g(A),f(A))
122	  - \operatorname{Cov}\bigl(\mathbb{E}[g(A)\mid A^*],\;\mathbb{E}[f(A)\mid A^*]\bigr).
123	  \label{eq:lotc}
124	\end{equation}
125	
126	At $C=I$: $\mathbb{E}[g\mid A^*]=g(A)$, so the between-group covariance equals $\operatorname{Cov}(g,f)$ and $B(I)=0$.
127	
128	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ (uniform, $A^*\perp A$): $\mathbb{E}[g\mid A^*]$ is constant, so the between-group covariance is zero and
129	\begin{equation}
130	  B_{\mathrm{OV}} \;\equiv\; B\bigl(\tfrac{1}{K}\mathbf{1}\mathbf{1}^\top\bigr)
131	  = \frac{\operatorname{Cov}(g(A),\,f(A))}{\operatorname{Var}(T)},
132	  \label{eq:bov}
133	\end{equation}
134	which equals the classical omitted-variable bias (no control for $A$).
135	
136	\paragraph{Sign preservation condition.}
137	Since $D(C)>0$, sign$(\operatorname{plim}\hat\tau) = $ sign$(\tau\cdot D(C) + R(C))$.
138	For sign preservation, it suffices that $R(C)$ does not overwhelm $\tau\cdot D(C)$.
139	
140	\begin{proposition}[Confounding sign preservation --- proportional case]
141	\label{prop:conf_prop}
142	If $f(A) = \lambda\,g(A)$ for some constant $\lambda$ (i.e., the confounder effects on $T$ and $Y$ are proportional), then
143	\begin{equation}
144	  B(C) = \bigl(1-\eta(C)\bigr)\,B_{\mathrm{OV}},
145	  \label{eq:convex}
146	\end{equation}
147	where
148	\[
149	  \eta(C) = \frac{\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])\;\sigma_T^2}
150	  {\operatorname{Var}(g(A))\bigl(\operatorname{Var}(g(A))-\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])+\sigma_T^2\bigr)}
151	  \;\in\;[0,1].
152	\]
153	Consequently, $B(C)$ lies between $0$ and $B_{\mathrm{OV}}$, and $\operatorname{sign}(\operatorname{plim}\hat\tau)=\operatorname{sign}(\tau)$ whenever $\operatorname{sign}(\tau)=\operatorname{sign}(\tau+B_{\mathrm{OV}})$.
154	\end{proposition}
155	
156	\begin{proof}
157	When $f=\lambda g$: the between-group covariance in~\eqref{eq:lotc} becomes $\lambda\,\operatorname{Var}(\mathbb{E}[g\mid A^*])$, and $\operatorname{Cov}(g,f)=\lambda\,\operatorname{Var}(g)$.
158	So $R(C)=\lambda\bigl(\operatorname{Var}(g)-\operatorname{Var}(\mathbb{E}[g\mid A^*])\bigr)=\lambda\,V_W$, where $V_W=\operatorname{Var}(g)-V_B$ with $V_B=\operatorname{Var}(\mathbb{E}[g\mid A^*])$.
159	Similarly, $D(C)=V_W+\sigma_T^2$.
160	Hence
161	\[
162	  B(C) = \frac{\lambda\,V_W}{V_W+\sigma_T^2},\qquad
163	  B_{\mathrm{OV}} = \frac{\lambda\,V}{V+\sigma_T^2},
164	\]
165	where $V=\operatorname{Var}(g)=V_B+V_W$.
166	The ratio
167	\[
168	  \frac{B(C)}{B_{\mathrm{OV}}} = \frac{V_W(V+\sigma_T^2)}{V(V_W+\sigma_T^2)} = 1 - \eta(C)
169	\]
170	is a decreasing function of $V_B\in[0,V]$.
171	At $V_B=0$ (no classification, $C$ uniform): $\eta=0$, $B=B_{\mathrm{OV}}$.
172	At $V_B=V$ (perfect classification, $C=I$): $\eta=1$, $B=0$.
173	Since $0\leq V_B\leq V$, we have $\eta\in[0,1]$ and $B(C)\in[0,B_{\mathrm{OV}}]$ (with the sign of $B_{\mathrm{OV}}$).
174	\end{proof}
175	
176	\begin{proposition}[Confounding sign preservation --- general case]
177	\label{prop:conf_gen}
178	For general $g$ and $f$ (not necessarily proportional), define the worst-case bias bound
179	\begin{equation}
180	  \bar{B} \;=\; \frac{\sqrt{\operatorname{Var}(g(A))\,\operatorname{Var}(f(A))}}{\sigma_T^2}.
181	  \label{eq:bbar}
182	\end{equation}
183	If $|\tau| > \bar{B}$, then $\operatorname{sign}(\operatorname{plim}\hat\tau(C))=\operatorname{sign}(\tau)$ for \emph{all} column-stochastic $C$.
184	\end{proposition}
185	
186	\begin{proof}
187	We need $\operatorname{sign}(\tau\cdot D(C)+R(C))=\operatorname{sign}(\tau)$, which holds if $|R(C)|<|\tau|\cdot D(C)$.
188	Since $D(C)\geq\sigma_T^2$ (shown in Lemma~\ref{lem:bias_decomp}), it suffices to show $|R(C)|<|\tau|\,\sigma_T^2$.
189	
190	\emph{Step 1: Bound $|R(C)|$.}
191	$R(C)=\mathbb{E}[\operatorname{Cov}(g(A),f(A)\mid A^*)]$.
192	By the Cauchy--Schwarz inequality applied to each within-group covariance:
193	\[
194	  |\operatorname{Cov}(g,f\mid A^*{=}j)|
195	  \leq \sqrt{\operatorname{Var}(g\mid A^*{=}j)\,\operatorname{Var}(f\mid A^*{=}j)}.
196	\]
197	Taking expectations and applying Cauchy--Schwarz again:
198	\begin{align*}
199	  |R(C)|
200	  &\leq \mathbb{E}\bigl[\sqrt{\operatorname{Var}(g\mid A^*)\,\operatorname{Var}(f\mid A^*)}\bigr]\\
201	  &\leq \sqrt{\mathbb{E}[\operatorname{Var}(g\mid A^*)]\;\mathbb{E}[\operatorname{Var}(f\mid A^*)]}\\
202	  &\leq \sqrt{\operatorname{Var}(g(A))\;\operatorname{Var}(f(A))},
203	\end{align*}
204	where the last step uses $\mathbb{E}[\operatorname{Var}(X\mid Y)]\leq\operatorname{Var}(X)$ (law of total variance).
205	
206	\emph{Step 2: Conclude.}
207	The bias satisfies
208	\[
209	  |B(C)| = \frac{|R(C)|}{D(C)} \leq \frac{\sqrt{\operatorname{Var}(g)\,\operatorname{Var}(f)}}{\sigma_T^2} = \bar{B}.
210	\]
211	When $|\tau|>\bar{B}$, the bias cannot cancel $\tau$, so $\operatorname{sign}(\operatorname{plim}\hat\tau)=\operatorname{sign}(\tau)$ for all $C$.
212	\end{proof}
213	
214	\paragraph{Relationship to the omitted-variable condition.}
215	A weaker (necessary) condition for sign preservation is $\operatorname{sign}(\tau)=\operatorname{sign}(\tau_{\mathrm{OV}})$ where $\tau_{\mathrm{OV}}=\tau+\operatorname{Cov}(g,f)/\operatorname{Var}(T)$.
216	If this fails, then $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ (uniform noise) already flips the sign.
217	The rigorous sufficient condition $|\tau|>\bar{B}$ implies the weaker condition, since $|B_{\mathrm{OV}}|=|\operatorname{Cov}(g,f)|/\operatorname{Var}(T)\leq\bar{B}$ by Cauchy--Schwarz and $\operatorname{Var}(T)\geq\sigma_T^2$.
218	
219	\paragraph{Verification for paper parameters ($K{=}3$).}
220	With $\tau{=}2.0$, $\boldsymbol{\alpha}{=}(1.5,{-}1.0)$, $\boldsymbol{\beta}^{(A)}{=}(1.0,{-}0.5)$, $\sigma_T{=}1.0$, $\mathbf{p}{=}(0.40,0.35,0.25)$:
221	\begin{align*}
222	  \operatorname{Var}(g) &= \sum_k p_k\alpha_k^2 - \bigl(\textstyle\sum_k p_k\alpha_k\bigr)^2 = 0.962,\\
223	  \operatorname{Var}(f) &= \sum_k p_k(\beta_k^{(A)})^2 - \bigl(\textstyle\sum_k p_k\beta_k^{(A)}\bigr)^2 = 0.362,\\
224	  \bar{B} &= \sqrt{0.962\times 0.362}\;/\;1.0^2 = 0.590.
225	\end{align*}
226	Since $|\tau|{=}2.0 > \bar{B}{=}0.590$, sign preservation is guaranteed for \emph{all} column-stochastic $C$ by Proposition~\ref{prop:conf_gen}.
227	Additionally, $B_{\mathrm{OV}}=\operatorname{Cov}(g,f)/\operatorname{Var}(T)=0.588/1.962={+}0.300$, giving $\tau_{\mathrm{OV}}{=}2.300>0$, confirming that both the necessary and sufficient conditions are satisfied.
228	
229	\paragraph{Extension to $K > 3$.}
230	For $K{>}3$, treatment effect coefficients are drawn from a fixed pool with alternating signs and decreasing magnitudes: $\boldsymbol{\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3, \ldots)$, truncated to $K$ entries. The category distribution uses $p_k \propto 1/(k{+}1)$, normalized to sum to 1. Other topology-specific parameters (confounding strengths, mediator effects, etc.) follow analogous alternating-sign pools. For $K{=}10$, $\boldsymbol{\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3)$.
231	
232	\subsection{Proof of Theorem~\ref{thm:monotone} (Confounding Monotonicity)}
233	\label{app:monotonicity_proof}
234	
235	Under the interpolation $C(\delta)=(1{-}\delta)I+\delta C_0$, we prove $|B(C(\delta))|$ is non-decreasing in $\delta$ for proportional effects ($f=\lambda g$) and provide numerical verification for the general case.
236	
237	\paragraph{Proportional case ($f=\lambda g$).}
238	From Proposition~\ref{prop:conf_prop}, $B(C)=\lambda V_W/(V_W+\sigma_T^2)$ where $V_W=\operatorname{Var}(g)-V_B$ and $V_B(\delta)=\operatorname{Var}(\mathbb{E}[g(A)\mid A^*_\delta])$.
239	
240	\emph{Step 1: $V_B(\delta)$ is non-increasing.}
241	The conditional expectation $\mathbb{E}[g(A)\mid A^*_\delta]$ is a linear function of the posterior $P(A\mid A^*_\delta)$, which in turn depends on $C(\delta)$.
242	As $\delta$ increases, $C(\delta)$ becomes a noisier channel: the mutual information $I(A;A^*_\delta)$ decreases.
243	While the exact degradation factorization $C(\delta_2)=M\cdot C(\delta_1)$ for a stochastic $M$ is non-trivial for the linear interpolation family, the monotonic decrease of $V_B(\delta)$ can be verified directly: for $K{=}2$ symmetric $C_0$, $dV_B/d\delta < 0$ follows by differentiation; for general $K$, we verify $V_B(\delta_2)\leq V_B(\delta_1)$ numerically across all test configurations with zero violations.
244	
245	\emph{Step 2: $|B(\delta)|$ is non-decreasing.}
246	$V_W(\delta)=\operatorname{Var}(g)-V_B(\delta)$ is non-decreasing (Step~1).
247	The function $h(x)=|\lambda|\,x/(x+\sigma_T^2)$ is strictly increasing for $x\geq 0$ and $\sigma_T^2>0$.
248	Hence $|B(\delta)|=h(V_W(\delta))$ is non-decreasing.
249	
250	\paragraph{General case.}
251	$|B(C(\delta))|\leq\bar{B}(\delta)$ where $\bar{B}(\delta)=\sqrt{\mathbb{E}[\operatorname{Var}(g\mid A^*_\delta)]\,\mathbb{E}[\operatorname{Var}(f\mid A^*_\delta)]}\,/\,D(\delta)$ (Proposition~\ref{prop:conf_gen}).
252	By the same reasoning (noisier $A^*_\delta$ reduces the explained variance), each $\mathbb{E}[\operatorname{Var}(\cdot\mid A^*_\delta)]$ is non-decreasing in $\delta$, and $D(\delta)=\mathbb{E}[\operatorname{Var}(T\mid A^*_\delta)]$ is non-decreasing.
253	The numerator grows at least as fast as the denominator (since $D(\delta)\leq\operatorname{Var}(T)$), maintaining monotonicity of the bound.
254	Extended verification (10{,}000 random $C_0$ matrices, $K \in \{3,5,7\}$) reveals worst-case step deviations of 0.011 (confounding), confirming approximate tightness; a strict monotonicity proof for the general case remains open.
255	
256	\subsection{Mediation Topology ($A$ = Mediator)}
257	\label{app:mediation}
258	
259	\paragraph{Data-generating process.}
260	$T\to A\to Y$, $T\to Y$.
261	\begin{align*}
262	  T &\sim \operatorname{Bernoulli}(0.5),\\
263	  A\mid T &\sim \operatorname{Categorical}\bigl(\operatorname{softmax}(\boldsymbol{\gamma}+\boldsymbol{\delta}\,T)\bigr),\\
264	  Y &= \tau_{\mathrm{dir}}\,T + f(A) + \varepsilon_Y.
265	\end{align*}
266	
267	\paragraph{Bias decomposition.}
268	By Lemma~\ref{lem:bias_decomp}, the direct-effect estimator satisfies:
269	\begin{equation}
270	  \operatorname{plim}\hat\tau_{\mathrm{dir}}(C) = \tau_{\mathrm{dir}} + \frac{\mathbb{E}[\operatorname{Cov}(T,\,f(A)\mid A^*)]}{D(C)}.
271	  \label{eq:med_bias}
272	\end{equation}
273	
274	The key structural difference from confounding: $T$ \emph{causes} $A$, so the residual covariance $\operatorname{Cov}(T,f(A)\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.
275	
276	\paragraph{Endpoint analysis.}
277	
278	At $C=I$ ($A^*{=}A$): conditioning on $A$ blocks the mediated path $T\to A\to Y$, so $\operatorname{Cov}(T,f(A)\mid A)=0$ and $\operatorname{plim}\hat\tau=\tau_{\mathrm{dir}}$.
279	
280	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ ($A^*\perp A$): no information about $A$ is used, and
281	\begin{align*}
282	  \mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)] &= \operatorname{Cov}(T,f(A)),\\
283	  D(C) &= \operatorname{Var}(T) = 0.25.
284	\end{align*}
285	The indirect effect is $\tau_{\mathrm{ind}}=\mathbb{E}[f(A)\mid T{=}1]-\mathbb{E}[f(A)\mid T{=}0]$, and
286	\[
287	  \operatorname{Cov}(T,f(A)) = 0.25\,\tau_{\mathrm{ind}}.
288	\]
289	Hence at $C$ uniform: $\operatorname{plim}\hat\tau = \tau_{\mathrm{dir}}+\tau_{\mathrm{ind}} = \tau_{\mathrm{total}}$.
290	
291	\paragraph{Numerical Verification (Mediation sign preservation).}
292	\label{find:med_sign}
293	$\operatorname{sign}(\operatorname{plim}\hat\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{dir}})$ whenever $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$, where $\tau_{\mathrm{total}}=\tau_{\mathrm{dir}}+\tau_{\mathrm{ind}}$.
294	This result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$; a closed-form proof for general $K$ remains open.
295	
296	\begin{proof}
297	Let $R(C)=\mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)]$ and $D(C)=\mathbb{E}[\operatorname{Var}(T\mid A^*)]>0$.
298	
299	\emph{Endpoints.}
300	At $C{=}I$: $f(A)$ is constant given $A{=}A^*$, so $R(I)=0$ and $B(I)=0$.
301	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$: $R=\operatorname{Cov}(T,f(A))=0.25\,\tau_{\mathrm{ind}}$ and $D=\operatorname{Var}(T)=0.25$, giving $B=\tau_{\mathrm{ind}}$.
302	
303	\emph{Within-group structure for binary $T$.}
304	Since $T\in\{0,1\}$, the within-$A^*$-group bias admits a revealing decomposition.
305	Let $p_j=P(T{=}1\mid A^*{=}j)$.
306	Then $\operatorname{Var}(T\mid A^*{=}j)=p_j(1{-}p_j)$ and
307	\[
308	  \operatorname{Cov}(T,f(A)\mid A^*{=}j)
309	  = p_j(1{-}p_j)\bigl[\mathbb{E}[f(A)\mid T{=}1,A^*{=}j]-\mathbb{E}[f(A)\mid T{=}0,A^*{=}j]\bigr].
310	\]
311	Define $\delta_j=\mathbb{E}[f(A)\mid T{=}1,A^*{=}j]-\mathbb{E}[f(A)\mid T{=}0,A^*{=}j]$ as the \emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.
312	Then
313	\[
314	  B(C)=\frac{R(C)}{D(C)}
315	  =\frac{\sum_j q_j\,p_j(1{-}p_j)\,\delta_j}{\sum_j q_j\,p_j(1{-}p_j)}
316	  =\sum_j w_j\,\delta_j,
317	\]
318	a weighted average of the conditional indirect effects, with weights $w_j=q_j p_j(1{-}p_j)/\sum_\ell q_\ell p_\ell(1{-}p_\ell)\geq 0$ summing to 1.
319	
320	At $C{=}I$: each $A^*{=}j$ group has $A{=}j$ a.s., so $\delta_j=f(j)-f(j)=0$ and $B=0$.
321	At $C$ uniform: $\delta_j=\tau_{\mathrm{ind}}$ for all $j$ and $B=\tau_{\mathrm{ind}}$.
322	
323	\emph{Sign preservation.}
324	When $\operatorname{Cov}(g(A),f(A))>0$ (the indirect effect reinforces the direct effect, i.e., $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{ind}}$ have the same sign), the bias $B(C)\geq 0$ cannot oppose $\tau_{\mathrm{dir}}$, so sign is preserved trivially.
325	
326	When $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{ind}}$ have opposite signs but $|\tau_{\mathrm{ind}}|<|\tau_{\mathrm{dir}}|$ (i.e., $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$), sign reversal requires some $|\delta_j|>|\tau_{\mathrm{dir}}|$ with the opposing sign.
327	Since each $\delta_j$ is a difference of weighted averages of $f$ values (with weights $P(A{=}k\mid T{=}t,A^*{=}j)$), and $B(C)$ is a convex combination of $\delta_j$, the bound $|B(C)|\leq\max_j|\delta_j|$ holds.
328	We verify numerically that $\max_j|\delta_j|\leq|\tau_{\mathrm{ind}}|$ for all 100{,}000 random $C$ matrices in our experiments, confirming sign preservation.
329	\end{proof}
330	
331	\paragraph{Verification for paper parameters ($K{=}3$).}
332	With $\tau_{\mathrm{dir}}{=}0.5$, $\boldsymbol{\gamma}{=}(0,0,0)$, $\boldsymbol{\delta}{=}(0,0.8,{-}0.6)$, $\boldsymbol{\beta}{=}(0,1.0,{-}0.5)$:
333	
334	$\tau_{\mathrm{ind}}=\mathbb{E}[f(A)\mid T{=}1]-\mathbb{E}[f(A)\mid T{=}0]=0.351$ (computed from the softmax class probabilities).
335	$\tau_{\mathrm{total}}=0.5+0.351=0.851>0$.
336	Since $\tau_{\mathrm{dir}}{>}0$ and $\tau_{\mathrm{total}}{>}0$, sign preservation holds for all $C$.
337	
338	\paragraph{Mediation monotonicity (proportional effects).}
339	\label{par:med_monotone}
340	
341	Under the interpolation $C(\delta)=(1{-}\delta)I+\delta C_0$, we prove $|B(C(\delta))|$ is non-decreasing in $\delta$ when the mediator's effect on $Y$ is proportional to its informativeness about $T$: $f(A)=\lambda\,g(A)$ for some scalar $\lambda$, where $g(k)=\mathbb{E}[T\mid A{=}k]$.
342	
343	\emph{Step 1: Decompose $T$ via the mediator.}
344	Define $g(A)=\mathbb{E}[T\mid A]$ and $\varepsilon_T = T - g(A)$.
345	By construction, $\mathbb{E}[\varepsilon_T\mid A]=0$.
346	By non-differential misclassification ($T\perp A^*\mid A$):
347	$\mathbb{E}[\varepsilon_T\mid A{=}k, A^*{=}j] = 0$,
348	so $\mathbb{E}[\varepsilon_T\mid A^*{=}j]=0$ and $\operatorname{Cov}(\varepsilon_T,\,g(A)\mid A^*{=}j)=0$ for every $j$.
349	
350	\emph{Step 2: Reduce the numerator.}
351	Since $f=\lambda g$:
352	\begin{align*}
353	  R(C) &= \lambda\,\mathbb{E}[\operatorname{Var}(g(A)\mid A^*)] = \lambda\,V_W.
354	\end{align*}
355	
356	\emph{Step 3: Constant additive term in denominator.}
357	\begin{align*}
358	  D(C) &= \mathbb{E}[\operatorname{Var}(T\mid A^*)]
359	       = V_W + \sigma_\varepsilon^2,
360	\end{align*}
361	where $\sigma_\varepsilon^2\equiv\mathbb{E}[\operatorname{Var}(\varepsilon_T\mid A^*)]$.
362	This is \emph{constant} (independent of $C$):
363	$\mathbb{E}[\operatorname{Var}(\varepsilon_T\mid A^*)]
364	  = \sum_k p_k\,\operatorname{Var}(T\mid A{=}k)
365	  = \mathbb{E}[\operatorname{Var}(T\mid A)]$,
366	where the equality uses column-stochasticity: $\sum_j q_j\,P(A{=}k\mid A^*{=}j)=p_k$.
367	
368	\emph{Step 4: Closed form and monotonicity.}
369	$B(C) = \lambda\,V_W/(V_W+\sigma_\varepsilon^2)$,
370	structurally identical to confounding (Proposition~\ref{prop:conf_prop}) with $\sigma_\varepsilon^2$ playing the role of $\sigma_T^2$.
371	Since $V_W(\delta)$ is non-decreasing (same argument as \S\ref{app:monotonicity_proof}, Step~1: $V_B(\delta)$ is a rational function of $\delta$ with non-positive derivative) and $h(x)=|\lambda|x/(x+\sigma_\varepsilon^2)$ is increasing, $|B(C(\delta))|$ is non-decreasing.
372	
373	\paragraph{Boundedness of the leakage coefficient.}
374	
375	The mediation bias~\eqref{eq:mediation} writes the residual indirect effect as $(1-\lambda(C))\,\tau_{\mathrm{ind}}$, which (for $\tau_{\mathrm{ind}}\neq 0$) \emph{implicitly} defines
376	\begin{equation}
377	\label{eq:lambda_def}
378	  \lambda(C) \;:=\; 1-\frac{B(C)}{\tau_{\mathrm{ind}}},\qquad
379	  B(C)\;\equiv\;\operatorname{plim}\hat{\tau}_{\mathrm{dir}}(A^*)-\tau_{\mathrm{dir}},\quad
380	  \tau_{\mathrm{ind}}\;=\;\frac{\operatorname{Cov}(T,f(A))}{\operatorname{Var}(T)}.
381	\end{equation}
382	Substituting back into~\eqref{eq:mediation} gives the convex-combination form
383	$\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)=\lambda(C)\,\tau_{\mathrm{dir}}+(1-\lambda(C))\,\tau_{\mathrm{total}}$, so $\lambda(C)$ is the weight placing the biased plim between $\tau_{\mathrm{dir}}$ (perfect classification) and $\tau_{\mathrm{total}}$ (no information).
384	
385	\begin{proposition}[Mediation leakage boundedness]
386	\label{prop:lambda_bound}
387	Let $\lambda(C)$ be defined by~\eqref{eq:lambda_def} with $\tau_{\mathrm{ind}}\neq 0$, and let $C$ be column-stochastic.
388	\begin{enumerate}
389	\item[(a)] $\lambda(C)\leq 1$ iff $\operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$ (the bias points in the direction of the indirect effect; no overcorrection).
390	\item[(b)] $\lambda(C)\geq 0$ iff additionally $|B(C)|\leq|\tau_{\mathrm{ind}}|$ (the bias does not exceed the indirect effect in magnitude).
391	\end{enumerate}
392	Equivalently, $\lambda(C)\in[0,1]$ iff $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)\in[\min(\tau_{\mathrm{dir}},\tau_{\mathrm{total}}),\,\max(\tau_{\mathrm{dir}},\tau_{\mathrm{total}})]$.
393	
394	Under \emph{proportional effects} ($f(A)=\lambda_0\,g(A)$ with $g(k)=\mathbb{E}[T\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\lambda(C)\in[0,1]$ unconditionally.
395	For \emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[f\mid A^*])$ may differ in sign or magnitude from $\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.
396	The endpoints $\lambda(I)=1$ and $\lambda(C)\to 0$ in the rank-one (uninformative) limit hold in all regimes.
397	
398	\emph{Sign preservation.} When $\lambda(C)\in[0,1]$, the convex-combination form gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)\in[\min(\tau_{\mathrm{dir}},\tau_{\mathrm{total}}),\,\max(\tau_{\mathrm{dir}},\tau_{\mathrm{total}})]$. If additionally $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$, both endpoints share the same sign, so $\operatorname{sign}(\operatorname{plim}\hat\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{dir}})$ for every~$C$. Under proportional effects, $\lambda(C)\in[0,1]$ is automatic (above), so sign preservation of $\hat\tau_{\mathrm{dir}}$ reduces to the single condition $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
399	\end{proposition}
400	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5c713d1e-235e-43e5-a90e-fe45e90bab1f",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "56276d19-38e4-485b-b19c-781fa6abce36",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\section{Proofs of Proposition~\\ref{prop:signflip} and Theorem~\\ref{thm:monotone}}\n\\label{app:proof}\n\nWe provide algebraic proofs of sign preservation for the confounding and collider topologies (Proposition~\\ref{prop:signflip}(a)--(b)), an explicit counterexample for exposure (Proposition~\\ref{prop:signflip}(c)), numerical verification for mediation, M-bias, and front-door (Numerical Verification~1), and the monotonicity proof for confounding (Theorem~\\ref{thm:monotone}).\nThroughout, $A\\in\\{0,1,\\dots,K{-}1\\}$ with prior $p_k=P(A{=}k)$, and $C$ is a $K{\\times}K$ column-stochastic confusion matrix with $C_{jk}=P(A^*{=}j\\mid A{=}k)$.\nWe use category~0 as the reference and let $D_j=\\mathbf{1}(A{=}j)$, $D_j^*=\\mathbf{1}(A^*{=}j)$ for $j=1,\\dots,K{-}1$.\n\n\\subsection{Notation and Key Identities}\n\\label{app:notation}\n\nUnder non-differential misclassification, the misclassified moments factor linearly through $C$.\nDefine the population vectors:\n\\begin{align}\n  q_j &= P(A^*{=}j) = \\textstyle\\sum_k C_{jk}\\,p_k, \\label{eq:q}\\\\\n  \\mathrm{ct}_j &= \\mathbb{E}[T\\cdot D_j^*] = \\textstyle\\sum_k C_{jk}\\,\\mathbb{E}[T\\cdot D_k], \\label{eq:ct}\\\\\n  \\mathrm{cy}_j &= \\mathbb{E}[Y\\cdot D_j^*] = \\textstyle\\sum_k C_{jk}\\,\\mathbb{E}[Y\\cdot D_k]. \\label{eq:cy}\n\\end{align}\nWrite $q = Cp$, $\\mathrm{ct} = C\\,\\mathbb{E}[T\\cdot D]$, and $\\mathrm{cy} = C\\,\\mathbb{E}[Y\\cdot D]$, where $D=(D_0,\\dots,D_{K-1})^\\top$.\n\n\\subsection{Frisch--Waugh--Lovell Decomposition}\n\\label{app:fwl}\n\nFor topologies where $T$ is directly observed (confounding, mediation, collider, M-bias, front-door), the estimator regresses $Y$ on $Z^*=(1,T,D_1^*,\\dots,D_{K-1}^*)$.\nBy the Frisch--Waugh--Lovell (FWL) theorem, the coefficient on $T$ satisfies:\n\\begin{equation}\n  \\operatorname{plim}\\hat{\\tau}(C)\n  = \\frac{\\mathbb{E}[\\tilde{T}\\,\\tilde{Y}]}{\\mathbb{E}[\\tilde{T}^2]},\n  \\label{eq:fwl}\n\\end{equation}\nwhere $\\tilde{T}=T-\\mathbb{E}[T\\mid A^*]$ and $\\tilde{Y}=Y-\\mathbb{E}[Y\\mid A^*]$ are residuals from projecting onto $(1,D_1^*,\\dots,D_{K-1}^*)$.\n\n\\begin{lemma}[Bias decomposition]\n\\label{lem:bias_decomp}\nSuppose $Y = \\tau T + f(A) + \\varepsilon_Y$ with $\\varepsilon_Y \\perp (T, A, A^*)$.\nThen\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C) = \\tau + \\frac{R(C)}{D(C)},\n  \\label{eq:bias_decomp}\n\\end{equation}\nwhere\n\\begin{align}\n  R(C) &= \\mathbb{E}\\bigl[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)\\bigr], \\label{eq:R}\\\\\n  D(C) &= \\mathbb{E}\\bigl[\\operatorname{Var}(T\\mid A^*)\\bigr] > 0. \\label{eq:D}\n\\end{align}\n\\end{lemma}\n\n\\begin{proof}\nExpand $\\tilde{Y}$ using $Y=\\tau T + f(A) + \\varepsilon_Y$:\n\\[\n  \\tilde{Y} = \\tau\\,\\tilde{T} + \\bigl(f(A) - \\mathbb{E}[f(A)\\mid A^*]\\bigr) + \\varepsilon_Y.\n\\]\nSince $\\tilde{T}$ is measurable w.r.t.\\ $(T,A^*)$ and $\\varepsilon_Y\\perp(T,A,A^*)$:\n\\[\n  \\mathbb{E}[\\tilde{T}\\,\\tilde{Y}]\n  = \\tau\\,\\mathbb{E}[\\tilde{T}^2]\n  + \\mathbb{E}\\bigl[\\tilde{T}\\,\\bigl(f(A)-\\mathbb{E}[f(A)\\mid A^*]\\bigr)\\bigr].\n\\]\nThe numerator residual is $R(C) = \\mathbb{E}[\\tilde{T}(f(A)-\\mathbb{E}[f(A)\\mid A^*])]$, and the denominator is $D(C) = \\mathbb{E}[\\tilde{T}^2]$.\n\nBy the law of total covariance:\n\\[\n  R(C) = \\sum_{j=0}^{K-1} q_j\\,\\operatorname{Cov}(T,\\,f(A)\\mid A^*{=}j)\n  = \\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)].\n\\]\nFor $D(C)>0$: decompose $T = g(A) + \\varepsilon_T$ where $g(A)=\\mathbb{E}[T\\mid A]$ (for confounding) or simply note that $T$ has exogenous variation independent of $A^*$ (for mediation).\nIn both cases, $\\tilde{T}=\\bigl(g(A)-\\mathbb{E}[g(A)\\mid A^*]\\bigr)+\\varepsilon_T'$, where $\\varepsilon_T'$ is the component of $T$ independent of $(A,A^*)$.\nHence $D(C)\\geq\\operatorname{Var}(\\varepsilon_T')>0$.\n\\end{proof}\n\n\\subsection{Confounding Topology ($A$ = Confounder)}\n\\label{app:confounding}\n\n\\paragraph{Data-generating process.}\n$A\\to T$, $A\\to Y$, $T\\to Y$.\nUsing dummy coding with category 0 as reference:\n\\begin{align*}\n  T &= \\sum_{j=1}^{K-1}\\alpha_j D_j + \\varepsilon_T,\\quad\n  \\varepsilon_T\\sim\\mathcal{N}(0,\\sigma_T^2),\\;\\varepsilon_T\\perp A,\\\\\n  Y &= \\tau\\, T + \\sum_{j=1}^{K-1}\\beta_j^{(A)} D_j + \\varepsilon_Y,\\quad\n  \\varepsilon_Y\\sim\\mathcal{N}(0,1),\\;\\varepsilon_Y\\perp(T,A).\n\\end{align*}\nDefine $g(k)=\\sum_{j}\\alpha_j\\mathbf{1}(k{=}j)$ and $f(k)=\\sum_{j}\\beta_j^{(A)}\\mathbf{1}(k{=}j)$, so $g(0)=f(0)=0$.\n\n\\paragraph{Closed-form plim.}\nUsing the FWL decomposition, the coefficient on $T$ is:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C)\n  = \\frac{\\mu_{TY} - \\sum_{j=0}^{K-1}\\frac{\\mathrm{ct}_j\\,\\mathrm{cy}_j}{q_j}}\n  {s_T - \\sum_{j=0}^{K-1}\\frac{\\mathrm{ct}_j^2}{q_j}},\n  \\label{eq:plim_conf}\n\\end{equation}\nwhere $s_T=\\mathbb{E}[T^2]$, $\\mu_{TY}=\\mathbb{E}[TY]$, and $\\mathrm{ct}_j$, $\\mathrm{cy}_j$, $q_j$ are defined in~\\eqref{eq:q}--\\eqref{eq:cy}.\n\n\\begin{proof}[Derivation]\nBy FWL, $\\operatorname{plim}\\hat\\tau = \\mathbb{E}[\\tilde{T}Y]/\\mathbb{E}[\\tilde{T}^2]$ where $\\tilde{T}=T-\\mathbb{E}[T\\mid A^*]$.\nSince $\\mathbb{E}[T\\mid A^*{=}j]=\\mathrm{ct}_j/q_j$:\n\\begin{align*}\n  \\mathbb{E}[\\tilde{T}^2]\n  &= \\mathbb{E}[T^2] - \\sum_j q_j\\bigl(\\mathrm{ct}_j/q_j\\bigr)^2\n  = s_T - \\sum_j \\mathrm{ct}_j^2/q_j,\\\\\n  \\mathbb{E}[\\tilde{T}\\,Y]\n  &= \\mathbb{E}[TY] - \\sum_j \\bigl(\\mathrm{ct}_j/q_j\\bigr)\\,\\mathbb{E}[Y\\cdot D_j^*]\n  = \\mu_{TY} - \\sum_j \\mathrm{ct}_j\\,\\mathrm{cy}_j/q_j.\n\\end{align*}\n\\end{proof}\n\n\\paragraph{Verification at $C=I$.}\nWhen $C=I$: $q_j=p_j$, $\\mathrm{ct}_j=\\mathbb{E}[T D_j]=\\alpha_j p_j$, $\\mathrm{cy}_j=\\mathbb{E}[Y D_j]=p_j(\\tau\\alpha_j+\\beta_j^{(A)})$.\nDirect substitution yields numerator $= \\tau\\sigma_T^2$ and denominator $= \\sigma_T^2$, giving $\\operatorname{plim}\\hat\\tau = \\tau$.\n\n\\paragraph{Bias structure.}\nBy Lemma~\\ref{lem:bias_decomp}:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C) = \\tau + B(C),\\quad\n  B(C) = \\frac{\\mathbb{E}[\\operatorname{Cov}(g(A),\\,f(A)\\mid A^*)]}{D(C)}.\n  \\label{eq:bias_conf}\n\\end{equation}\nBy the law of total covariance:\n\\begin{equation}\n  \\mathbb{E}[\\operatorname{Cov}(g,f\\mid A^*)]\n  = \\operatorname{Cov}(g(A),f(A))\n  - \\operatorname{Cov}\\bigl(\\mathbb{E}[g(A)\\mid A^*],\\;\\mathbb{E}[f(A)\\mid A^*]\\bigr).\n  \\label{eq:lotc}\n\\end{equation}\n\nAt $C=I$: $\\mathbb{E}[g\\mid A^*]=g(A)$, so the between-group covariance equals $\\operatorname{Cov}(g,f)$ and $B(I)=0$.\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ (uniform, $A^*\\perp A$): $\\mathbb{E}[g\\mid A^*]$ is constant, so the between-group covariance is zero and\n\\begin{equation}\n  B_{\\mathrm{OV}} \\;\\equiv\\; B\\bigl(\\tfrac{1}{K}\\mathbf{1}\\mathbf{1}^\\top\\bigr)\n  = \\frac{\\operatorname{Cov}(g(A),\\,f(A))}{\\operatorname{Var}(T)},\n  \\label{eq:bov}\n\\end{equation}\nwhich equals the classical omitted-variable bias (no control for $A$).\n\n\\paragraph{Sign preservation condition.}\nSince $D(C)>0$, sign$(\\operatorname{plim}\\hat\\tau) = $ sign$(\\tau\\cdot D(C) + R(C))$.\nFor sign preservation, it suffices that $R(C)$ does not overwhelm $\\tau\\cdot D(C)$.\n\n\\begin{proposition}[Confounding sign preservation --- proportional case]\n\\label{prop:conf_prop}\nIf $f(A) = \\lambda\\,g(A)$ for some constant $\\lambda$ (i.e., the confounder effects on $T$ and $Y$ are proportional), then\n\\begin{equation}\n  B(C) = \\bigl(1-\\eta(C)\\bigr)\\,B_{\\mathrm{OV}},\n  \\label{eq:convex}\n\\end{equation}\nwhere\n\\[\n  \\eta(C) = \\frac{\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])\\;\\sigma_T^2}\n  {\\operatorname{Var}(g(A))\\bigl(\\operatorname{Var}(g(A))-\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])+\\sigma_T^2\\bigr)}\n  \\;\\in\\;[0,1].\n\\]\nConsequently, $B(C)$ lies between $0$ and $B_{\\mathrm{OV}}$, and $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau)=\\operatorname{sign}(\\tau)$ whenever $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau+B_{\\mathrm{OV}})$.\n\\end{proposition}\n\n\\begin{proof}\nWhen $f=\\lambda g$: the between-group covariance in~\\eqref{eq:lotc} becomes $\\lambda\\,\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])$, and $\\operatorname{Cov}(g,f)=\\lambda\\,\\operatorname{Var}(g)$.\nSo $R(C)=\\lambda\\bigl(\\operatorname{Var}(g)-\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])\\bigr)=\\lambda\\,V_W$, where $V_W=\\operatorname{Var}(g)-V_B$ with $V_B=\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])$.\nSimilarly, $D(C)=V_W+\\sigma_T^2$.\nHence\n\\[\n  B(C) = \\frac{\\lambda\\,V_W}{V_W+\\sigma_T^2},\\qquad\n  B_{\\mathrm{OV}} = \\frac{\\lambda\\,V}{V+\\sigma_T^2},\n\\]\nwhere $V=\\operatorname{Var}(g)=V_B+V_W$.\nThe ratio\n\\[\n  \\frac{B(C)}{B_{\\mathrm{OV}}} = \\frac{V_W(V+\\sigma_T^2)}{V(V_W+\\sigma_T^2)} = 1 - \\eta(C)\n\\]\nis a decreasing function of $V_B\\in[0,V]$.\nAt $V_B=0$ (no classification, $C$ uniform): $\\eta=0$, $B=B_{\\mathrm{OV}}$.\nAt $V_B=V$ (perfect classification, $C=I$): $\\eta=1$, $B=0$.\nSince $0\\leq V_B\\leq V$, we have $\\eta\\in[0,1]$ and $B(C)\\in[0,B_{\\mathrm{OV}}]$ (with the sign of $B_{\\mathrm{OV}}$).\n\\end{proof}\n\n\\begin{proposition}[Confounding sign preservation --- general case]\n\\label{prop:conf_gen}\nFor general $g$ and $f$ (not necessarily proportional), define the worst-case bias bound\n\\begin{equation}\n  \\bar{B} \\;=\\; \\frac{\\sqrt{\\operatorname{Var}(g(A))\\,\\operatorname{Var}(f(A))}}{\\sigma_T^2}.\n  \\label{eq:bbar}\n\\end{equation}\nIf $|\\tau| > \\bar{B}$, then $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau(C))=\\operatorname{sign}(\\tau)$ for \\emph{all} column-stochastic $C$.\n\\end{proposition}\n\n\\begin{proof}\nWe need $\\operatorname{sign}(\\tau\\cdot D(C)+R(C))=\\operatorname{sign}(\\tau)$, which holds if $|R(C)|<|\\tau|\\cdot D(C)$.\nSince $D(C)\\geq\\sigma_T^2$ (shown in Lemma~\\ref{lem:bias_decomp}), it suffices to show $|R(C)|<|\\tau|\\,\\sigma_T^2$.\n\n\\emph{Step 1: Bound $|R(C)|$.}\n$R(C)=\\mathbb{E}[\\operatorname{Cov}(g(A),f(A)\\mid A^*)]$.\nBy the Cauchy--Schwarz inequality applied to each within-group covariance:\n\\[\n  |\\operatorname{Cov}(g,f\\mid A^*{=}j)|\n  \\leq \\sqrt{\\operatorname{Var}(g\\mid A^*{=}j)\\,\\operatorname{Var}(f\\mid A^*{=}j)}.\n\\]\nTaking expectations and applying Cauchy--Schwarz again:\n\\begin{align*}\n  |R(C)|\n  &\\leq \\mathbb{E}\\bigl[\\sqrt{\\operatorname{Var}(g\\mid A^*)\\,\\operatorname{Var}(f\\mid A^*)}\\bigr]\\\\\n  &\\leq \\sqrt{\\mathbb{E}[\\operatorname{Var}(g\\mid A^*)]\\;\\mathbb{E}[\\operatorname{Var}(f\\mid A^*)]}\\\\\n  &\\leq \\sqrt{\\operatorname{Var}(g(A))\\;\\operatorname{Var}(f(A))},\n\\end{align*}\nwhere the last step uses $\\mathbb{E}[\\operatorname{Var}(X\\mid Y)]\\leq\\operatorname{Var}(X)$ (law of total variance).\n\n\\emph{Step 2: Conclude.}\nThe bias satisfies\n\\[\n  |B(C)| = \\frac{|R(C)|}{D(C)} \\leq \\frac{\\sqrt{\\operatorname{Var}(g)\\,\\operatorname{Var}(f)}}{\\sigma_T^2} = \\bar{B}.\n\\]\nWhen $|\\tau|>\\bar{B}$, the bias cannot cancel $\\tau$, so $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau)=\\operatorname{sign}(\\tau)$ for all $C$.\n\\end{proof}\n\n\\paragraph{Relationship to the omitted-variable condition.}\nA weaker (necessary) condition for sign preservation is $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau_{\\mathrm{OV}})$ where $\\tau_{\\mathrm{OV}}=\\tau+\\operatorname{Cov}(g,f)/\\operatorname{Var}(T)$.\nIf this fails, then $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ (uniform noise) already flips the sign.\nThe rigorous sufficient condition $|\\tau|>\\bar{B}$ implies the weaker condition, since $|B_{\\mathrm{OV}}|=|\\operatorname{Cov}(g,f)|/\\operatorname{Var}(T)\\leq\\bar{B}$ by Cauchy--Schwarz and $\\operatorname{Var}(T)\\geq\\sigma_T^2$.\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\tau{=}2.0$, $\\boldsymbol{\\alpha}{=}(1.5,{-}1.0)$, $\\boldsymbol{\\beta}^{(A)}{=}(1.0,{-}0.5)$, $\\sigma_T{=}1.0$, $\\mathbf{p}{=}(0.40,0.35,0.25)$:\n\\begin{align*}\n  \\operatorname{Var}(g) &= \\sum_k p_k\\alpha_k^2 - \\bigl(\\textstyle\\sum_k p_k\\alpha_k\\bigr)^2 = 0.962,\\\\\n  \\operatorname{Var}(f) &= \\sum_k p_k(\\beta_k^{(A)})^2 - \\bigl(\\textstyle\\sum_k p_k\\beta_k^{(A)}\\bigr)^2 = 0.362,\\\\\n  \\bar{B} &= \\sqrt{0.962\\times 0.362}\\;/\\;1.0^2 = 0.590.\n\\end{align*}\nSince $|\\tau|{=}2.0 > \\bar{B}{=}0.590$, sign preservation is guaranteed for \\emph{all} column-stochastic $C$ by Proposition~\\ref{prop:conf_gen}.\nAdditionally, $B_{\\mathrm{OV}}=\\operatorname{Cov}(g,f)/\\operatorname{Var}(T)=0.588/1.962={+}0.300$, giving $\\tau_{\\mathrm{OV}}{=}2.300>0$, confirming that both the necessary and sufficient conditions are satisfied.\n\n\\paragraph{Extension to $K > 3$.}\nFor $K{>}3$, treatment effect coefficients are drawn from a fixed pool with alternating signs and decreasing magnitudes: $\\boldsymbol{\\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3, \\ldots)$, truncated to $K$ entries. The category distribution uses $p_k \\propto 1/(k{+}1)$, normalized to sum to 1. Other topology-specific parameters (confounding strengths, mediator effects, etc.) follow analogous alternating-sign pools. For $K{=}10$, $\\boldsymbol{\\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3)$.\n\n\\subsection{Proof of Theorem~\\ref{thm:monotone} (Confounding Monotonicity)}\n\\label{app:monotonicity_proof}\n\nUnder the interpolation $C(\\delta)=(1{-}\\delta)I+\\delta C_0$, we prove $|B(C(\\delta))|$ is non-decreasing in $\\delta$ for proportional effects ($f=\\lambda g$) and provide numerical verification for the general case.\n\n\\paragraph{Proportional case ($f=\\lambda g$).}\nFrom Proposition~\\ref{prop:conf_prop}, $B(C)=\\lambda V_W/(V_W+\\sigma_T^2)$ where $V_W=\\operatorname{Var}(g)-V_B$ and $V_B(\\delta)=\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*_\\delta])$.\n\n\\emph{Step 1: $V_B(\\delta)$ is non-increasing.}\nThe conditional expectation $\\mathbb{E}[g(A)\\mid A^*_\\delta]$ is a linear function of the posterior $P(A\\mid A^*_\\delta)$, which in turn depends on $C(\\delta)$.\nAs $\\delta$ increases, $C(\\delta)$ becomes a noisier channel: the mutual information $I(A;A^*_\\delta)$ decreases.\nWhile the exact degradation factorization $C(\\delta_2)=M\\cdot C(\\delta_1)$ for a stochastic $M$ is non-trivial for the linear interpolation family, the monotonic decrease of $V_B(\\delta)$ can be verified directly: for $K{=}2$ symmetric $C_0$, $dV_B/d\\delta < 0$ follows by differentiation; for general $K$, we verify $V_B(\\delta_2)\\leq V_B(\\delta_1)$ numerically across all test configurations with zero violations.\n\n\\emph{Step 2: $|B(\\delta)|$ is non-decreasing.}\n$V_W(\\delta)=\\operatorname{Var}(g)-V_B(\\delta)$ is non-decreasing (Step~1).\nThe function $h(x)=|\\lambda|\\,x/(x+\\sigma_T^2)$ is strictly increasing for $x\\geq 0$ and $\\sigma_T^2>0$.\nHence $|B(\\delta)|=h(V_W(\\delta))$ is non-decreasing.\n\n\\paragraph{General case.}\n$|B(C(\\delta))|\\leq\\bar{B}(\\delta)$ where $\\bar{B}(\\delta)=\\sqrt{\\mathbb{E}[\\operatorname{Var}(g\\mid A^*_\\delta)]\\,\\mathbb{E}[\\operatorname{Var}(f\\mid A^*_\\delta)]}\\,/\\,D(\\delta)$ (Proposition~\\ref{prop:conf_gen}).\nBy the same reasoning (noisier $A^*_\\delta$ reduces the explained variance), each $\\mathbb{E}[\\operatorname{Var}(\\cdot\\mid A^*_\\delta)]$ is non-decreasing in $\\delta$, and $D(\\delta)=\\mathbb{E}[\\operatorname{Var}(T\\mid A^*_\\delta)]$ is non-decreasing.\nThe numerator grows at least as fast as the denominator (since $D(\\delta)\\leq\\operatorname{Var}(T)$), maintaining monotonicity of the bound.\nExtended verification (10{,}000 random $C_0$ matrices, $K \\in \\{3,5,7\\}$) reveals worst-case step deviations of 0.011 (confounding), confirming approximate tightness; a strict monotonicity proof for the general case remains open.\n\n\\subsection{Mediation Topology ($A$ = Mediator)}\n\\label{app:mediation}\n\n\\paragraph{Data-generating process.}\n$T\\to A\\to Y$, $T\\to Y$.\n\\begin{align*}\n  T &\\sim \\operatorname{Bernoulli}(0.5),\\\\\n  A\\mid T &\\sim \\operatorname{Categorical}\\bigl(\\operatorname{softmax}(\\boldsymbol{\\gamma}+\\boldsymbol{\\delta}\\,T)\\bigr),\\\\\n  Y &= \\tau_{\\mathrm{dir}}\\,T + f(A) + \\varepsilon_Y.\n\\end{align*}\n\n\\paragraph{Bias decomposition.}\nBy Lemma~\\ref{lem:bias_decomp}, the direct-effect estimator satisfies:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C) = \\tau_{\\mathrm{dir}} + \\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)]}{D(C)}.\n  \\label{eq:med_bias}\n\\end{equation}\n\nThe key structural difference from confounding: $T$ \\emph{causes} $A$, so the residual covariance $\\operatorname{Cov}(T,f(A)\\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.\n\n\\paragraph{Endpoint analysis.}\n\nAt $C=I$ ($A^*{=}A$): conditioning on $A$ blocks the mediated path $T\\to A\\to Y$, so $\\operatorname{Cov}(T,f(A)\\mid A)=0$ and $\\operatorname{plim}\\hat\\tau=\\tau_{\\mathrm{dir}}$.\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ ($A^*\\perp A$): no information about $A$ is used, and\n\\begin{align*}\n  \\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)] &= \\operatorname{Cov}(T,f(A)),\\\\\n  D(C) &= \\operatorname{Var}(T) = 0.25.\n\\end{align*}\nThe indirect effect is $\\tau_{\\mathrm{ind}}=\\mathbb{E}[f(A)\\mid T{=}1]-\\mathbb{E}[f(A)\\mid T{=}0]$, and\n\\[\n  \\operatorname{Cov}(T,f(A)) = 0.25\\,\\tau_{\\mathrm{ind}}.\n\\]\nHence at $C$ uniform: $\\operatorname{plim}\\hat\\tau = \\tau_{\\mathrm{dir}}+\\tau_{\\mathrm{ind}} = \\tau_{\\mathrm{total}}$.\n\n\\paragraph{Numerical Verification (Mediation sign preservation).}\n\\label{find:med_sign}\n$\\operatorname{sign}(\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{dir}})$ whenever $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$, where $\\tau_{\\mathrm{total}}=\\tau_{\\mathrm{dir}}+\\tau_{\\mathrm{ind}}$.\nThis result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$; a closed-form proof for general $K$ remains open.\n\n\\begin{proof}\nLet $R(C)=\\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)]$ and $D(C)=\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]>0$.\n\n\\emph{Endpoints.}\nAt $C{=}I$: $f(A)$ is constant given $A{=}A^*$, so $R(I)=0$ and $B(I)=0$.\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$: $R=\\operatorname{Cov}(T,f(A))=0.25\\,\\tau_{\\mathrm{ind}}$ and $D=\\operatorname{Var}(T)=0.25$, giving $B=\\tau_{\\mathrm{ind}}$.\n\n\\emph{Within-group structure for binary $T$.}\nSince $T\\in\\{0,1\\}$, the within-$A^*$-group bias admits a revealing decomposition.\nLet $p_j=P(T{=}1\\mid A^*{=}j)$.\nThen $\\operatorname{Var}(T\\mid A^*{=}j)=p_j(1{-}p_j)$ and\n\\[\n  \\operatorname{Cov}(T,f(A)\\mid A^*{=}j)\n  = p_j(1{-}p_j)\\bigl[\\mathbb{E}[f(A)\\mid T{=}1,A^*{=}j]-\\mathbb{E}[f(A)\\mid T{=}0,A^*{=}j]\\bigr].\n\\]\nDefine $\\delta_j=\\mathbb{E}[f(A)\\mid T{=}1,A^*{=}j]-\\mathbb{E}[f(A)\\mid T{=}0,A^*{=}j]$ as the \\emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.\nThen\n\\[\n  B(C)=\\frac{R(C)}{D(C)}\n  =\\frac{\\sum_j q_j\\,p_j(1{-}p_j)\\,\\delta_j}{\\sum_j q_j\\,p_j(1{-}p_j)}\n  =\\sum_j w_j\\,\\delta_j,\n\\]\na weighted average of the conditional indirect effects, with weights $w_j=q_j p_j(1{-}p_j)/\\sum_\\ell q_\\ell p_\\ell(1{-}p_\\ell)\\geq 0$ summing to 1.\n\nAt $C{=}I$: each $A^*{=}j$ group has $A{=}j$ a.s., so $\\delta_j=f(j)-f(j)=0$ and $B=0$.\nAt $C$ uniform: $\\delta_j=\\tau_{\\mathrm{ind}}$ for all $j$ and $B=\\tau_{\\mathrm{ind}}$.\n\n\\emph{Sign preservation.}\nWhen $\\operatorname{Cov}(g(A),f(A))>0$ (the indirect effect reinforces the direct effect, i.e., $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{ind}}$ have the same sign), the bias $B(C)\\geq 0$ cannot oppose $\\tau_{\\mathrm{dir}}$, so sign is preserved trivially.\n\nWhen $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{ind}}$ have opposite signs but $|\\tau_{\\mathrm{ind}}|<|\\tau_{\\mathrm{dir}}|$ (i.e., $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$), sign reversal requires some $|\\delta_j|>|\\tau_{\\mathrm{dir}}|$ with the opposing sign.\nSince each $\\delta_j$ is a difference of weighted averages of $f$ values (with weights $P(A{=}k\\mid T{=}t,A^*{=}j)$), and $B(C)$ is a convex combination of $\\delta_j$, the bound $|B(C)|\\leq\\max_j|\\delta_j|$ holds.\nWe verify numerically that $\\max_j|\\delta_j|\\leq|\\tau_{\\mathrm{ind}}|$ for all 100{,}000 random $C$ matrices in our experiments, confirming sign preservation.\n\\end{proof}\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\tau_{\\mathrm{dir}}{=}0.5$, $\\boldsymbol{\\gamma}{=}(0,0,0)$, $\\boldsymbol{\\delta}{=}(0,0.8,{-}0.6)$, $\\boldsymbol{\\beta}{=}(0,1.0,{-}0.5)$:\n\n$\\tau_{\\mathrm{ind}}=\\mathbb{E}[f(A)\\mid T{=}1]-\\mathbb{E}[f(A)\\mid T{=}0]=0.351$ (computed from the softmax class probabilities).\n$\\tau_{\\mathrm{total}}=0.5+0.351=0.851>0$.\nSince $\\tau_{\\mathrm{dir}}{>}0$ and $\\tau_{\\mathrm{total}}{>}0$, sign preservation holds for all $C$.\n\n\\paragraph{Mediation monotonicity (proportional effects).}\n\\label{par:med_monotone}\n\nUnder the interpolation $C(\\delta)=(1{-}\\delta)I+\\delta C_0$, we prove $|B(C(\\delta))|$ is non-decreasing in $\\delta$ when the mediator's effect on $Y$ is proportional to its informativeness about $T$: $f(A)=\\lambda\\,g(A)$ for some scalar $\\lambda$, where $g(k)=\\mathbb{E}[T\\mid A{=}k]$.\n\n\\emph{Step 1: Decompose $T$ via the mediator.}\nDefine $g(A)=\\mathbb{E}[T\\mid A]$ and $\\varepsilon_T = T - g(A)$.\nBy construction, $\\mathbb{E}[\\varepsilon_T\\mid A]=0$.\nBy non-differential misclassification ($T\\perp A^*\\mid A$):\n$\\mathbb{E}[\\varepsilon_T\\mid A{=}k, A^*{=}j] = 0$,\nso $\\mathbb{E}[\\varepsilon_T\\mid A^*{=}j]=0$ and $\\operatorname{Cov}(\\varepsilon_T,\\,g(A)\\mid A^*{=}j)=0$ for every $j$.\n\n\\emph{Step 2: Reduce the numerator.}\nSince $f=\\lambda g$:\n\\begin{align*}\n  R(C) &= \\lambda\\,\\mathbb{E}[\\operatorname{Var}(g(A)\\mid A^*)] = \\lambda\\,V_W.\n\\end{align*}\n\n\\emph{Step 3: Constant additive term in denominator.}\n\\begin{align*}\n  D(C) &= \\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]\n       = V_W + \\sigma_\\varepsilon^2,\n\\end{align*}\nwhere $\\sigma_\\varepsilon^2\\equiv\\mathbb{E}[\\operatorname{Var}(\\varepsilon_T\\mid A^*)]$.\nThis is \\emph{constant} (independent of $C$):\n$\\mathbb{E}[\\operatorname{Var}(\\varepsilon_T\\mid A^*)]\n  = \\sum_k p_k\\,\\operatorname{Var}(T\\mid A{=}k)\n  = \\mathbb{E}[\\operatorname{Var}(T\\mid A)]$,\nwhere the equality uses column-stochasticity: $\\sum_j q_j\\,P(A{=}k\\mid A^*{=}j)=p_k$.\n\n\\emph{Step 4: Closed form and monotonicity.}\n$B(C) = \\lambda\\,V_W/(V_W+\\sigma_\\varepsilon^2)$,\nstructurally identical to confounding (Proposition~\\ref{prop:conf_prop}) with $\\sigma_\\varepsilon^2$ playing the role of $\\sigma_T^2$.\nSince $V_W(\\delta)$ is non-decreasing (same argument as \\S\\ref{app:monotonicity_proof}, Step~1: $V_B(\\delta)$ is a rational function of $\\delta$ with non-positive derivative) and $h(x)=|\\lambda|x/(x+\\sigma_\\varepsilon^2)$ is increasing, $|B(C(\\delta))|$ is non-decreasing.\n\n\\paragraph{Boundedness of the leakage coefficient.}\n\nThe mediation bias~\\eqref{eq:mediation} writes the residual indirect effect as $(1-\\lambda(C))\\,\\tau_{\\mathrm{ind}}$, which (for $\\tau_{\\mathrm{ind}}\\neq 0$) \\emph{implicitly} defines\n\\begin{equation}\n\\label{eq:lambda_def}\n  \\lambda(C) \\;:=\\; 1-\\frac{B(C)}{\\tau_{\\mathrm{ind}}},\\qquad\n  B(C)\\;\\equiv\\;\\operatorname{plim}\\hat{\\tau}_{\\mathrm{dir}}(A^*)-\\tau_{\\mathrm{dir}},\\quad\n  \\tau_{\\mathrm{ind}}\\;=\\;\\frac{\\operatorname{Cov}(T,f(A))}{\\operatorname{Var}(T)}.\n\\end{equation}\nSubstituting back into~\\eqref{eq:mediation} gives the convex-combination form\n$\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)=\\lambda(C)\\,\\tau_{\\mathrm{dir}}+(1-\\lambda(C))\\,\\tau_{\\mathrm{total}}$, so $\\lambda(C)$ is the weight placing the biased plim between $\\tau_{\\mathrm{dir}}$ (perfect classification) and $\\tau_{\\mathrm{total}}$ (no information).\n\n\\begin{proposition}[Mediation leakage boundedness]\n\\label{prop:lambda_bound}\nLet $\\lambda(C)$ be defined by~\\eqref{eq:lambda_def} with $\\tau_{\\mathrm{ind}}\\neq 0$, and let $C$ be column-stochastic.\n\\begin{enumerate}\n\\item[(a)] $\\lambda(C)\\leq 1$ iff $\\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$ (the bias points in the direction of the indirect effect; no overcorrection).\n\\item[(b)] $\\lambda(C)\\geq 0$ iff additionally $|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$ (the bias does not exceed the indirect effect in magnitude).\n\\end{enumerate}\nEquivalently, $\\lambda(C)\\in[0,1]$ iff $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)\\in[\\min(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}}),\\,\\max(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}})]$.\n\nUnder \\emph{proportional effects} ($f(A)=\\lambda_0\\,g(A)$ with $g(k)=\\mathbb{E}[T\\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\\lambda(C)\\in[0,1]$ unconditionally.\nFor \\emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[f\\mid A^*])$ may differ in sign or magnitude from $\\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.\nThe endpoints $\\lambda(I)=1$ and $\\lambda(C)\\to 0$ in the rank-one (uninformative) limit hold in all regimes.\n\n\\emph{Sign preservation.} When $\\lambda(C)\\in[0,1]$, the convex-combination form gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)\\in[\\min(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}}),\\,\\max(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}})]$. If additionally $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$, both endpoints share the same sign, so $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{dir}})$ for every~$C$. Under proportional effects, $\\lambda(C)\\in[0,1]$ is automatic (above), so sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ reduces to the single condition $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\n\\end{proposition}\n",
      "numLines": 400,
      "startLine": 1,
      "totalLines": 1066
    }
  },
  "sourceToolAssistantUUID": "5c713d1e-235e-43e5-a90e-fe45e90bab1f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-22T16:55:18.233Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NKHeE6bpSTKj7Jef9hgQrd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 400,
  "limit": 400
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "56276d19-38e4-485b-b19c-781fa6abce36",
  "isSidechain": false,
  "requestId": "req_011CbHxXNoxomAT9RQrVeqyM",
  "type": "assistant",
  "uuid": "51c40010-83f4-4e7b-85a7-e1207a22013d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NwHn6cF84EpseTEsBq4AwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13201,
      "cache_read_input_tokens": 30449,
      "output_tokens": 279,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13201,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 279,
          "cache_read_input_tokens": 30449,
          "cache_creation_input_tokens": 13201,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13201
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

_source line 41_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "51c40010-83f4-4e7b-85a7-e1207a22013d",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Tool result

_source line 42 · 2026-05-22T16:55:18.760Z_

<details><summary>↩ Tool result · `toolu_01NKHeE6bpSTKj7Jef9hgQrd`</summary>

```text
400	
401	\begin{proof}
402	\emph{(a),(b).} With $\tau_{\mathrm{ind}}\neq 0$, $\lambda(C)\leq 1\iff B(C)/\tau_{\mathrm{ind}}\geq 0\iff \operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$. Given (a), $\lambda(C)\geq 0\iff B(C)/\tau_{\mathrm{ind}}\leq 1\iff|B(C)|\leq|\tau_{\mathrm{ind}}|$.
403	
404	\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\lambda_0\,V_W(C)/(V_W(C)+\sigma_\varepsilon^2)$; the rank-one limit $V_W{\to}V$ yields $\tau_{\mathrm{ind}}=\lambda_0\,V/(V+\sigma_\varepsilon^2)$. Both quantities carry $\operatorname{sign}(\lambda_0)$, establishing~(a). The ratio
405	\[
406	  \frac{B(C)}{\tau_{\mathrm{ind}}}\;=\;\frac{V_W(C)\,(V+\sigma_\varepsilon^2)}{V\,(V_W(C)+\sigma_\varepsilon^2)}
407	\]
408	is monotone increasing in $V_W(C)\in[0,V]$ with range $[0,1]$ (its derivative in $V_W$ is $\sigma_\varepsilon^2(V+\sigma_\varepsilon^2)/[V(V_W+\sigma_\varepsilon^2)^2]>0$), establishing~(b). Hence $\lambda(C)\in[0,1]$ unconditionally.
409	
410	\emph{General case.} Substituting $\lambda(C)$ from~\eqref{eq:lambda_def} into~\eqref{eq:mediation} yields $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)=\lambda(C)\,\tau_{\mathrm{dir}}+(1{-}\lambda(C))\,\tau_{\mathrm{total}}$, so $\lambda(C)\in[0,1]$ iff $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{total}}$.
411	
412	\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\mathbb{E}[T\mid A^*]=g(A)$, and FWL gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\tau_{\mathrm{dir}}$, hence $B(I)=0$ and $\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\perp A$ so $\mathbb{E}[T\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\operatorname{Cov}(Y,T)/\operatorname{Var}(T)=\tau_{\mathrm{total}}$, giving $B=\tau_{\mathrm{ind}}$ and $\lambda=0$.
413	\end{proof}
414	
415	\paragraph{Relation to the between-variance ratio.}
416	A natural \emph{diagnostic} closely related to $\lambda(C)$ is the between-variance ratio
417	\begin{equation}
418	\label{eq:vb_ratio}
419	  \lambda_V(C) \;:=\; \frac{V_B(C)}{V},\qquad V_B(C)\;=\;\operatorname{Var}\!\bigl(\mathbb{E}[g(A)\mid A^*]\bigr),\quad V\;=\;\operatorname{Var}(g(A)),
420	\end{equation}
421	which satisfies $\lambda_V(C)\in[0,1]$ \emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\lambda$ and $\lambda_V$ agree at the endpoints and are related by
422	\[
423	  1-\lambda(C)\;=\;\frac{V_W(C)\,(V+\sigma_\varepsilon^2)}{V\,(V_W(C)+\sigma_\varepsilon^2)}\;=\;\bigl(1-\lambda_V(C)\bigr)\cdot\frac{V+\sigma_\varepsilon^2}{V_W(C)+\sigma_\varepsilon^2},
424	\]
425	so they coincide in the limit $\sigma_\varepsilon^2\gg V$. They generally differ for non-proportional $f$. We use $\lambda$ throughout the main text because it parameterizes~\eqref{eq:mediation} directly; $\lambda_V$ remains a useful summary of the channel quality of $A^*$ as a proxy for $A$ (independent of the structural form of $f$).
426	
427	\paragraph{Numerical verification.}
428	For each $K\in\{3,5,7\}$ we draw $N{=}10{,}000$ configurations $(\pi,g,\sigma_\varepsilon^2,C)$ with $\pi\sim\operatorname{Dirichlet}(\mathbf{1})$, $g\sim\mathcal{N}(0,I_K)$, $\sigma_\varepsilon^2\sim\operatorname{Uniform}(0.1,2)$, columns of $C\sim\operatorname{Dirichlet}(\mathbf{1})$, and evaluate $\lambda(C)$ from~\eqref{eq:lambda_def} in two regimes for $f$:
429	\begin{itemize}\itemsep0pt
430	\item \textbf{Proportional} ($f=\lambda_0\,g$, $\lambda_0\sim\mathcal{N}(0,1)\!\setminus\!\{0\}$): $\lambda(C)\in[0,1]$ in \emph{all} $30{,}000$ trials (pooled observed range $[1.2{\times}10^{-5},\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\hat\tau_{\mathrm{dir}}$ therefore reduces to $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
431	\item \textbf{Non-proportional} ($f\sim\mathcal{N}(0,I_K)$ drawn independently of $g$, restricted to $|\tau_{\mathrm{ind}}|\geq 0.05$ to avoid the ill-conditioned regime where $\lambda{=}1{-}B/\tau_{\mathrm{ind}}$ diverges): $\lambda(C)$ exceeds $[0,1]$ in $\sim15$--$17\%$ of trials, illustrating that (a) and (b) are not automatic outside the proportional case.
432	\end{itemize}
433	The diagnostic $\lambda_V(C)$ lies in $[0,1]$ across all $30{,}000$ trials irrespective of regime, as guaranteed by the law of total variance. The script and full results are in \texttt{artifacts/verify\_lambda\_bound.py} and \texttt{artifacts/verify\_lambda\_bound\_results.json}.
434	
435	\subsection{Collider Topology ($A$ = Collider)}
436	\label{app:collider}
437	
438	\paragraph{Data-generating process.}
439	$T\to A\leftarrow Y$, $T\to Y$.
440	The treatment effect is unconfounded:
441	\begin{align*}
442	  T &\sim \mathcal{N}(0,1),\quad
443	  Y = \tau\,T + \varepsilon_Y,\quad \varepsilon_Y\sim\mathcal{N}(0,1),\;\varepsilon_Y\perp T,\\
444	  A\mid T,Y &\sim \operatorname{Categorical}\bigl(\operatorname{softmax}(\boldsymbol{\delta}_T\,T + \boldsymbol{\delta}_Y\,Y)\bigr).
445	\end{align*}
446	The collider $A$ is a common \emph{effect} of $T$ and $Y$.
447	The no-control estimator (regressing $Y$ on $T$ alone) is consistent: $\operatorname{plim}\hat\tau_{\mathrm{nc}}=\tau$.
448	The researcher erroneously controls for $A^*$, inducing Berkson's bias.
449	
450	\paragraph{Bias decomposition.}
451	Unlike confounding, $\varepsilon_Y$ is not independent of $A$ (since $A$ depends on $Y=\tau T+\varepsilon_Y$), so Lemma~\ref{lem:bias_decomp} does not apply directly.
452	Instead, we derive the bias from the FWL identity~\eqref{eq:fwl}.
453	Writing $\tilde{Y}=\tau\tilde{T}+(\varepsilon_Y-\mathbb{E}[\varepsilon_Y\mid A^*])$ and noting that $\mathbb{E}[\tilde{T}\,\varepsilon_Y]=\mathbb{E}[\operatorname{Cov}(T,\varepsilon_Y\mid A^*)]$ (since $T\perp\varepsilon_Y$ unconditionally):
454	\begin{equation}
455	  \operatorname{plim}\hat\tau(C) = \tau + B(C),\quad
456	  B(C) = \frac{\mathbb{E}[\operatorname{Cov}(T,\,\varepsilon_Y\mid A^*)]}{\mathbb{E}[\operatorname{Var}(T\mid A^*)]}.
457	  \label{eq:bias_col}
458	\end{equation}
459	Under non-differential misclassification ($A^*\perp(T,\varepsilon_Y)\mid A$), define $g(k)=\mathbb{E}[T\mid A{=}k]$ and $h(k)=\mathbb{E}[\varepsilon_Y\mid A{=}k]$.
460	By the tower property, $\mathbb{E}[T\mid A^*]=\mathbb{E}[g(A)\mid A^*]$ and $\mathbb{E}[\varepsilon_Y\mid A^*]=\mathbb{E}[h(A)\mid A^*]$.
461	Since $\operatorname{Cov}(T,\varepsilon_Y)=0$, the law of total covariance gives:
462	\[
463	  B(C) = \frac{-\operatorname{Cov}\bigl(\mathbb{E}[g(A)\mid A^*],\;\mathbb{E}[h(A)\mid A^*]\bigr)}{\mathbb{E}[\operatorname{Var}(T\mid A^*)]}.
464	\]
465	
466	\paragraph{Endpoint analysis.}
467	At $C=I$ ($A^*{=}A$):
468	$B(I) = -\operatorname{Cov}(g(A),h(A))\,/\,\mathbb{E}[\operatorname{Var}(T\mid A)] = B_{\mathrm{Berkson}}$,
469	the full Berkson's bias from conditioning on the collider.
470	
471	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ ($A^*\perp A$):
472	$\mathbb{E}[g(A)\mid A^*]$ and $\mathbb{E}[h(A)\mid A^*]$ are constant, so $B=0$ and $\operatorname{plim}\hat\tau=\tau$.
473	
474	This is the structural reverse of confounding: misclassification attenuates the collider-induced bias toward zero, rather than growing bias from zero toward $B_{\mathrm{OV}}$.
475	
476	\begin{proposition}[Collider sign preservation --- proportional case]
477	\label{prop:col_prop}
478	If $h(A)=\lambda\,g(A)$ for some constant $\lambda$, then $|B(C)|\leq|B(I)|$ for all column-stochastic $C$, and $B(C)$ has the same sign as $B(I)$.
479	Consequently, $\operatorname{sign}(\operatorname{plim}\hat\tau)=\operatorname{sign}(\tau)$ whenever $\operatorname{sign}(\tau)=\operatorname{sign}(\tau+B_{\mathrm{Berkson}})$.
480	\end{proposition}
481	
482	\begin{proof}
483	When $h=\lambda g$, the numerator becomes $-\lambda\,\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])$ and the denominator is $\operatorname{Var}(T)-\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])$.
484	Let $V^*=\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])\in[0,V_g]$ where $V_g=\operatorname{Var}(g(A))$.
485	Then
486	\[
487	  |B(C)| = |\lambda|\,\frac{V^*}{\operatorname{Var}(T)-V^*}.
488	\]
489	The function $x\mapsto x/(a-x)$ is increasing on $[0,a)$.
490	With $a=\operatorname{Var}(T)>V_g\geq V^*$:
491	$|B(C)|\leq|\lambda|\,V_g/(\operatorname{Var}(T)-V_g)=|B(I)|$.
492	At $V^*{=}0$ (uniform $C$): $B{=}0$.  At $V^*{=}V_g$ ($C{=}I$): $B{=}B(I)$.
493	\end{proof}
494	
495	\begin{proposition}[Collider sign preservation --- general case]
496	\label{prop:col_gen}
497	Define
498	\begin{equation}
499	  \bar{B}_{\mathrm{col}} = \frac{\sqrt{\operatorname{Var}(g(A))\,\operatorname{Var}(h(A))}}{\mathbb{E}[\operatorname{Var}(T\mid A)]}.
500	  \label{eq:bbar_col}
501	\end{equation}
502	If $|\tau|>\bar{B}_{\mathrm{col}}$, then $\operatorname{sign}(\operatorname{plim}\hat\tau(C))=\operatorname{sign}(\tau)$ for all column-stochastic $C$.
503	\end{proposition}
504	
505	\begin{proof}
506	\emph{Step~1: Bound the numerator.}
507	By Cauchy--Schwarz:
508	$|\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[h\mid A^*])|\leq\sqrt{\operatorname{Var}(\mathbb{E}[g\mid A^*])\,\operatorname{Var}(\mathbb{E}[h\mid A^*])}$.
509	Since conditional expectation reduces variance: $\operatorname{Var}(\mathbb{E}[g\mid A^*])\leq\operatorname{Var}(g(A))$ and likewise for $h$.
510	
511	\emph{Step~2: Bound the denominator.}
512	$\mathbb{E}[\operatorname{Var}(T\mid A^*)]=\operatorname{Var}(T)-\operatorname{Var}(\mathbb{E}[T\mid A^*])\geq\operatorname{Var}(T)-\operatorname{Var}(g(A))=\mathbb{E}[\operatorname{Var}(T\mid A)]$.
513	
514	\emph{Step~3: Conclude.}
515	$|B(C)|\leq\sqrt{\operatorname{Var}(g)\,\operatorname{Var}(h)}\,/\,\mathbb{E}[\operatorname{Var}(T\mid A)]=\bar{B}_{\mathrm{col}}$.
516	When $|\tau|>\bar{B}_{\mathrm{col}}$, the bias cannot overwhelm $\tau$.
517	\end{proof}
518	
519	\paragraph{Verification for paper parameters ($K{=}3$).}
520	With $\tau{=}1.0$, $\boldsymbol{\delta}_T{=}(0,\,0.5,\,{-}0.3)$, $\boldsymbol{\delta}_Y{=}(0,\,0.8,\,0.6)$, from $5{\times}10^6$-sample Monte Carlo:
521	\begin{align*}
522	  \operatorname{Var}(g(A)) &= 0.187,\quad
523	  \operatorname{Var}(h(A)) = 0.076,\quad
524	  \mathbb{E}[\operatorname{Var}(T\mid A)] = 0.813,\\
525	  \bar{B}_{\mathrm{col}} &= \sqrt{0.187\times 0.076}\;/\;0.813 = 0.147.
526	\end{align*}
527	Since $|\tau|{=}1.0\gg\bar{B}_{\mathrm{col}}{=}0.147$, Proposition~\ref{prop:col_gen} guarantees sign preservation.
528	Additionally, $B_{\mathrm{Berkson}}{=}{-}0.114$, giving $\tau+B_{\mathrm{Berkson}}{=}0.886{>}0$.
529	Verified across $100{,}000$ random column-stochastic $C$: $\tau_{\mathrm{sign\,flip}}{=}0\%$, and $|B(C)|\leq|B_{\mathrm{Berkson}}|$ in all cases.
530	
531	\subsection{Front-door Topology ($A$ = Mediator under Confounding)}
532	\label{app:frontdoor}
533	
534	\paragraph{Data-generating process.}
535	$T\to A\to Y$, $U\to T$, $U\to Y$.
536	An unobserved confounder $U$ affects both treatment and outcome:
537	\begin{align*}
538	  U &\sim \mathcal{N}(0,1),\quad
539	  T = \alpha_U\,U + \eta,\quad \eta\sim\mathcal{N}(0,1),\;\eta\perp U,\\
540	  A\mid T &\sim \operatorname{Categorical}\bigl(\operatorname{softmax}(\boldsymbol{\gamma}+\boldsymbol{\delta}\,T)\bigr),\\
541	  Y &= f(A) + \lambda\,U + \varepsilon_Y,\quad \varepsilon_Y\perp(T,A,U).
542	\end{align*}
543	There is no direct $T{\to}Y$ edge; the causal effect of $T$ on $Y$ operates entirely through $A$.
544	The researcher controls for $A^*$ in $Y\sim 1+T+D_1^*+\cdots+D_{K-1}^*$.
545	
546	\paragraph{Bias decomposition.}
547	Since the direct effect is zero, the FWL coefficient on $T$ captures only bias:
548	\[
549	  \operatorname{plim}\hat\tau(C) = \frac{\mathbb{E}[\operatorname{Cov}(T,\,Y\mid A^*)]}{\mathbb{E}[\operatorname{Var}(T\mid A^*)]}.
550	\]
551	Substituting $Y=f(A)+\lambda U+\varepsilon_Y$ and using $\varepsilon_Y\perp(T,A,A^*)$:
552	\begin{equation}
553	  \operatorname{plim}\hat\tau(C)
554	  = \underbrace{\frac{\lambda\,\alpha_U}{\operatorname{Var}(T)}}_{\text{confounding (constant)}}
555	  \;+\; \underbrace{\frac{\mathbb{E}[\operatorname{Cov}(T,\,f(A)\mid A^*)]}{D(C)}}_{\displaystyle B_{\mathrm{med}}(C)},
556	  \label{eq:fd_decomp}
557	\end{equation}
558	where $D(C)=\mathbb{E}[\operatorname{Var}(T\mid A^*)]$.
559	
560	\begin{proof}[Derivation of~\eqref{eq:fd_decomp}]
561	Expand the numerator as
562	$\mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)] + \lambda\,\mathbb{E}[\operatorname{Cov}(T,U\mid A^*)]$.
563	For the confounding term: since $T=\alpha_U U+\eta$ with $(U,\eta)$ jointly Gaussian, the regression residual $\xi=U-\frac{\alpha_U}{\operatorname{Var}(T)}T$ satisfies $\xi\perp T$.
564	Because $A$ is a function of $T$ (plus independent softmax noise) and $A^*$ is a function of $A$ (plus independent misclassification noise), $\xi\perp(T,A,A^*)$.
565	Therefore
566	\[
567	  \operatorname{Cov}(T,U\mid A^*{=}j)
568	  = \frac{\alpha_U}{\operatorname{Var}(T)}\,\operatorname{Var}(T\mid A^*{=}j)
569	  \quad\forall\;j,
570	\]
571	and $\lambda\,\mathbb{E}[\operatorname{Cov}(T,U\mid A^*)]=\frac{\lambda\alpha_U}{\operatorname{Var}(T)}\,D(C)$, yielding the constant first term after division by $D(C)$.
572	\end{proof}
573	
574	This decomposition reveals that \emph{misclassification does not affect the confounding component}.
575	The confusion matrix $C$ modulates only the mediation-type leakage $B_{\mathrm{med}}(C)$, which has the same structure as in~§\ref{app:mediation}.
576	
577	\paragraph{Endpoint analysis.}
578	At $C=I$: $B_{\mathrm{med}}(I)=0$ (controlling $A$ blocks the $T\to A\to Y$ path), and $\operatorname{plim}\hat\tau(I)=\lambda\alpha_U/\operatorname{Var}(T)$ (pure confounding residual).
579	
580	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$: $B_{\mathrm{med}}=\operatorname{Cov}(T,f(A))/\operatorname{Var}(T)$, and $\operatorname{plim}\hat\tau_{\mathrm{nc}}=[\operatorname{Cov}(T,f(A))+\lambda\alpha_U]/\operatorname{Var}(T)$, the naive regression coefficient with no controls.
581	
582	\paragraph{Numerical Verification (Front-door sign preservation).}
583	\label{find:fd_sign}
584	Since $B_{\mathrm{med}}(C)$ has the same structure as the mediation bias (§\ref{app:mediation})---interpolating between $0$ at $C{=}I$ and $\operatorname{Cov}(T,f(A))/\operatorname{Var}(T)$ at $C$ uniform---sign preservation holds whenever the two endpoints have the same sign:
585	\[
586	  \operatorname{sign}\!\bigl(\lambda\alpha_U\bigr)
587	  = \operatorname{sign}\!\bigl(\lambda\alpha_U + \operatorname{Cov}(T,f(A))\bigr).
588	\]
589	This result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$.
590	
591	\paragraph{Verification for paper parameters ($K{=}3$).}
592	With $\alpha_U{=}1.0$, $\lambda{=}1.0$, $\boldsymbol{\beta}{=}(0,1.0,{-}0.5)$, $\boldsymbol{\gamma}{=}(0,0.5,{-}0.3)$, $\boldsymbol{\delta}{=}(0,1.0,{-}0.8)$:
593	\begin{align*}
594	  \lambda\alpha_U/\operatorname{Var}(T) &= 1.0\times 1.0\,/\,2.0 = 0.500,\\
595	  \operatorname{Cov}(T,f(A))/\operatorname{Var}(T) &= 0.594\,/\,2.0 = 0.297.
596	\end{align*}
597	Both components are positive, so $\operatorname{plim}\hat\tau(C)\in[0.500,\,0.797]>0$ for all $C$.
598	
599	\subsection{Exposure Topology: Sign Reversal Counterexample}
600	\label{app:exposure}
601	
602	\begin{proposition}[Exposure sign reversal]
603	\label{prop:exp_counter}
604	For $K{=}3$ with $A$ as the treatment variable, there exist a marginal distribution $\mathbf{p}$, treatment effects $\boldsymbol{\beta}$, and a column-stochastic $C$ with $C_{kk}>0.5$ for all $k$, such that $\operatorname{sign}(\operatorname{plim}\hat\beta_1)\neq\operatorname{sign}(\beta_1)$.
605	\end{proposition}
606	
607	\begin{proof}[Construction]
608	Consider the exposure DGP $Y = \beta_1 D_1 + \beta_2 D_2 + \varepsilon_Y$ with:
609	\begin{itemize}
610	  \item Uniform prior: $\mathbf{p}=(1/3,\,1/3,\,1/3)$.
611	  \item True effects: $\beta_1=1$,\; $\beta_2=-10$.
612	\end{itemize}
613	Choose the confusion matrix
614	\[
615	  C = \begin{pmatrix}
616	    0.60 & 0.10 & 0.10\\
617	    0.10 & 0.60 & 0.39\\
618	    0.30 & 0.30 & 0.51
619	  \end{pmatrix},\qquad
620	  C_{kk}\in\{0.60,\,0.60,\,0.51\},\;\text{all}>0.5.
621	\]
622	Column sums are $1$ (verifiable by inspection).
623	
624	The OLS estimator regresses $Y$ on $(1,D_1^*,D_2^*)$.
625	The plim of $\hat\beta_j$ equals $\mathbb{E}[Y\mid A^*{=}j]-\mathbb{E}[Y\mid A^*{=}0]$, where
626	\[
627	  \mathbb{E}[Y\mid A^*{=}j] = \sum_{k=0}^{2} P(A{=}k\mid A^*{=}j)\,\beta_k
628	  = \sum_{k=1}^{2}\frac{C_{jk}\,p_k}{q_j}\,\beta_k.
629	\]
630	
631	\emph{Marginal distribution of $A^*$:}
632	\begin{align*}
633	  q_0 &= \tfrac{1}{3}(0.60+0.10+0.10)=0.267,\\
634	  q_1 &= \tfrac{1}{3}(0.10+0.60+0.39)=0.363,\\
635	  q_2 &= \tfrac{1}{3}(0.30+0.30+0.51)=0.370.
636	\end{align*}
637	
638	\emph{Conditional means:}
639	\begin{align*}
640	  \mathbb{E}[Y\mid A^*{=}0]
641	  &= \frac{0.10\times\tfrac{1}{3}\times 1 + 0.10\times\tfrac{1}{3}\times({-}10)}{0.267}
642	  = \frac{0.0333-0.3333}{0.267} = -1.125,\\[4pt]
643	  \mathbb{E}[Y\mid A^*{=}1]
644	  &= \frac{0.60\times\tfrac{1}{3}\times 1 + 0.39\times\tfrac{1}{3}\times({-}10)}{0.363}
645	  = \frac{0.200-1.300}{0.363} = -3.028,\\[4pt]
646	  \mathbb{E}[Y\mid A^*{=}2]
647	  &= \frac{0.30\times\tfrac{1}{3}\times 1 + 0.51\times\tfrac{1}{3}\times({-}10)}{0.370}
648	  = \frac{0.100-1.700}{0.370} = -4.324.
649	\end{align*}
650	
651	\emph{Estimated coefficient:}
652	\[
653	  \operatorname{plim}\hat\beta_1 = \mathbb{E}[Y\mid A^*{=}1]-\mathbb{E}[Y\mid A^*{=}0]
654	  = -3.028-(-1.125) = \mathbf{-1.903}.
655	\]
656	The true $\beta_1=+1>0$ but $\operatorname{plim}\hat\beta_1=-1.903<0$: \textbf{sign reversal}.
657	
658	\emph{Mechanism.}
659	The large off-diagonal entry $C_{12}=0.39$ (probability of classifying true category~2 as $A^*{=}1$) routes substantial probability mass from category~2 ($\beta_2=-10$) into the $A^*{=}1$ bin.
660	Despite $C_{11}=0.60>0.5$, the contamination from the strongly negative $\beta_2$ overwhelms the positive $\beta_1$, reversing the sign of the estimated effect for category~1.
661	This failure mode is structurally impossible at $K{=}2$: a $2{\times}2$ column-stochastic matrix with $C_{kk}>0.5$ has the form $C=\bigl(\begin{smallmatrix}a&1{-}b\\1{-}a&b\end{smallmatrix}\bigr)$ with $a,b>0.5$, and the single coefficient $\hat\beta_1$ is a positive-weighted average of $\beta_1$, preserving sign.
662	For $K{\geq}3$, the additional degrees of freedom in $C$ permit cross-contamination between categories with opposite-sign effects.
663	\end{proof}
664	
665	\subsection{Summary of Conditions}
666	\label{app:conditions}
667	
668	\begin{table}[h]
669	\centering
670	\small
671	\begin{tabular}{lccc}
672	\toprule
673	\textbf{Topology} & \textbf{Sufficient condition} & \textbf{Status} & \textbf{Paper DGP} \\
674	\midrule
675	Confounding & $\operatorname{sign}(\tau)=\operatorname{sign}(\tau{+}B_{\mathrm{OV}})$ & Proved & $\checkmark$ ($2.0$ vs $2.3$)\\
676	Collider & $|\tau|>\bar{B}_{\mathrm{col}}$ (Prop.~\ref{prop:col_gen}) & Proved & $\checkmark$ ($1.0$ vs $0.15$)\\
677	\midrule
678	Mediation & $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$ & Empirical & $\checkmark$ ($0.5$ vs $0.85$)\\
679	M-bias & Bias is attenuating (toward $\tau$) & Empirical & $\checkmark$ \\
680	Front-door & $\operatorname{sign}(\lambda\alpha_U)=\operatorname{sign}(\lambda\alpha_U{+}\operatorname{Cov}(T,f))$ & Empirical & $\checkmark$ ($0.50$ vs $0.80$)\\
681	\midrule
682	Exposure & Not guaranteed for $K\geq 3$ & Counterex. & See §\ref{app:exposure} \\
683	IV & Not guaranteed (denominator instability) & --- & --- \\
684	\bottomrule
685	\end{tabular}
686	\caption{Sufficient conditions for sign preservation under non-differential misclassification.
687	``Proved'' = algebraic proof via Cauchy--Schwarz (confounding) or Berkson attenuation (collider).
688	``Empirical'' = verified across 100{,}000 random column-stochastic matrices with zero violations; analytic proof for general $K$ remains open.
689	All conditions are on DGP parameters (not on $C$): once satisfied, sign preservation holds for all column-stochastic $C$ with $C_{kk}>0$.}
690	\label{tab:sign_conditions}
691	\end{table}
692	
693	\paragraph{Structural argument for M-bias topology.}
694	\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.
695	Misclassification of $A$ weakens the statistical association along this backdoor path, reducing the spurious correlation rather than amplifying it.
696	The bias therefore interpolates between the full M-bias (perfect classification, $\delta{=}0$) and zero (no classification information, $\delta{\to}\delta_{\max}$), monotonically non-increasing in $\delta$.
697	
698	\paragraph{Remark.}
699	The sign preservation conditions for confounding, mediation, collider, and front-door are conditions on the DGP parameters (the relative strength of the causal effect versus the confounding, indirect, or collider-induced bias), not on the confusion matrix $C$.
700	Once the condition is satisfied, sign preservation holds for \emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.
701	Conversely, if the condition fails (i.e., the omitted-variable or total-effect estimate has the opposite sign from $\tau$), then there exist confusion matrices that produce sign reversal.
702	For the DGP parameters used throughout our experiments, the conditions are comfortably satisfied.
703	The sign-alignment condition is violated when the confounder has opposing effects on treatment and outcome (e.g., $\gamma_A > 0$ on $T$ but $\gamma_A < 0$ on $Y$), producing $\operatorname{sign}(\tau) \neq \operatorname{sign}(\tau_{\mathrm{OV}})$. In applied settings, such opposing effects are uncommon when the analyst adjusts for $A$ precisely because they believe it confounds the $T$--$Y$ relationship in a consistent direction. When the condition fails, sign reversal becomes possible under sufficient misclassification, though this represents a pathological DGP where adjustment itself may be questionable.
704	
705	\section{Supplementary Tables, Figures, and Algorithm}
706	\label{app:supplementary}
707	
708	\subsection{Binarization Collapse}
709	\label{app:binarization}
710	
711	Collapsing $K$-class annotations to binary before analysis discards multi-class error structure. We quantify ``binarization collapse'' as $\Delta = |\text{bias}_{K} - \text{bias}_{K \to 2}|$.
712	
713	For $K{=}3$, binarization introduces additional bias varying 154$\times$ across topologies: from $\bar{\Delta}{=}0.006$ (M-bias) to $\bar{\Delta}{=}0.926$ (IV). Exposure and IV also introduce sign flips during binarization (14\% and 17.5\%), a phenomenon absent in the other topologies (Figure~\ref{fig:binarization}).
714	
715	\begin{figure*}[h]
716	\centering
717	\includegraphics[width=\textwidth]{fig3_asv_ranking.pdf}
718	\caption{ASV sensitivity ranking across topologies. Three ASV types (magnitude, significance, sign-flip) reveal a topology-dependent vulnerability spectrum from IV (maximally fragile, 52.6\% sign reversal; sign-flip ASV $= 1.1$--$6.7$) to M-bias (immune, ASV $= \infty$).}
719	\label{fig:asv_ranking}
720	\end{figure*}
721	
722	\begin{table}[h]
723	\centering
724	\caption{ASV type applicability and sensitivity across DAG topologies. Magnitude ASV at $\tau{=}0.5$, 10\% threshold. Power at $\tau{=}0.05$ significance filter. ---: not applicable.}
725	\label{tab:asv_grid}
726	\small
727	\begin{tabular}{lcccl}
728	\toprule
729	\textbf{Topology} & \textbf{Mag. ASV} & \textbf{Signif.} & \textbf{Sign-flip} & \textbf{Rank} \\
730	\midrule
731	IV & 0.101--0.607 & 0\% & 1.1--6.7 & 1 (fragile) \\
732	Front-door & 0.064--0.387 & 100\% & --- & 2 \\
733	Confounding & 0.081--0.487 & 100\% & --- & 3 \\
734	Mediation & 0.076--0.454 & 0\% & --- & 4 \\
735	Collider & 0.338--2.028 & 0\% & --- & 5 \\
736	M-bias & $\infty$ & 96--100\% & --- & 6 (immune) \\
737	Exposure & --- & --- & 83.4\%$^*$ & --- \\
738	\bottomrule
739	\multicolumn{5}{l}{\scriptsize $^*$Fraction of $C_0$ with $\tau_{\text{sign\_flip}} < 1$. Exposure uses sign-flip ASV exclusively.}
740	\end{tabular}
741	\end{table}
742	
743	\begin{figure}[h]
744	\centering
745	\includegraphics[width=\columnwidth]{fig7_dirichlet_overlay.pdf}
746	\caption{Empirical LLM confusion matrices overlaid on theoretical violation-rate curves (exposure, left; IV, right). Theoretical curves are derived from $K{=}3$ Dirichlet random matrices; empirical points are positioned at their minimum diagonal entry. Markers denote datasets (circles: HumAID $K{=}10$; squares: VAST $K{=}3$; triangles: CivilComments $K{=}2$).}
747	\label{fig:dirichlet_overlay}
748	\end{figure}
749	
750	\begin{figure}[h]
751	\centering
752	\includegraphics[width=\columnwidth]{fig4_binarization.pdf}
753	\caption{Binarization collapse $\Delta$ across topologies. Collapsing $K{=}3$ annotations to binary introduces additional bias varying 154$\times$ from M-bias (0.006) to IV (0.926).}
754	\label{fig:binarization}
755	\end{figure}
756	
757	\begin{figure}[h]
758	\centering
759	\includegraphics[width=\columnwidth]{fig6_asv_heatmap.pdf}
760	\caption{ASV magnitude ranges across topologies for HumAID ($K{=}10$). Left: magnitude ASV ($\delta^*$) range across 8 LLM configurations; lower values indicate greater fragility. ``Safe'' topologies never exceed the 10\% bias threshold. Right: percentage of configurations flagged as ASV-unsafe.}
761	\label{fig:asv_heatmap}
762	\end{figure}
763	
764	\begin{table}[h]
765	\centering
766	\caption{RMSE reduction (\%) by correction method and DAG topology (mean across 6 error structures, $N_{\text{sim}}{=}1{,}000$). Positive = reduced RMSE; negative = increased RMSE. Naive/MLA show 0.0\% for FWL-invariant topologies because $C^{-1}$ cannot change the $T$ coefficient. \textbf{Bold}: best method per topology; \underline{underline}: best gold-free method.}
767	\label{tab:correction}
768	\small
769	\begin{tabular}{lccccc}
770	\toprule
771	\textbf{Topology} & \textbf{Naive} & \textbf{MLA} & \textbf{DSL} & \textbf{SIMEX} & \textbf{PPI++} \\
772	\midrule
773	Confounding & 0.0 & 0.0 & \underline{48.0} & 35.1 & \textbf{83.2} \\
774	Mediation & 0.0 & 0.0 & \underline{52.9} & 39.1 & \textbf{54.1} \\
775	Collider & 0.0 & 0.0 & $-$92.6 & \underline{31.8} & \textbf{50.5} \\
776	M-bias & 0.0 & 0.0 & $-$267 & \textbf{\underline{0.1}} & $-$88.0 \\
777	\midrule
778	Front-door & $-$52.7 & $-$111.5 & \underline{$-$29.0} & $-$62.4 & \textbf{74.1} \\
779	Exposure & $-$44.8 & $-$89.0 & $-$59.5 & \underline{$-$9.8} & \textbf{75.5} \\
780	IV & $-$40.4 & $-$58.7 & $-$206.1 & \underline{59.4} & \textbf{79.4} \\
781	\midrule
782	Grand mean & $-$19.7 & $-$37.0 & $-$79.0 & 13.3 & \textbf{47.0} \\
783	\bottomrule
784	\end{tabular}
785	\end{table}
786	
787	\paragraph{Error structures used in correction experiments.}
788	The six confusion matrix structures used for Table~\ref{tab:correction} are:
789	(1)~\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;
790	(2)~\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;
791	(3)~\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;
792	(4)~\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);
793	(5)~\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;
794	(6)~\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.
795	All are column-stochastic with $K{=}3$. Results are averaged across all six structures.
796	
797	\begin{algorithm}[h]
798	\caption{Correction method selection for LLM-annotated causal inference. Assumes linear structural equations; FWL-based routing may not apply under nonlinear models (see Appendix~\ref{sec:logistic_dgp}).}
799	\label{alg:correction}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "51c40010-83f4-4e7b-85a7-e1207a22013d",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "2048edc4-cc6c-4894-98e2-0b45f378636a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\n\\begin{proof}\n\\emph{(a),(b).} With $\\tau_{\\mathrm{ind}}\\neq 0$, $\\lambda(C)\\leq 1\\iff B(C)/\\tau_{\\mathrm{ind}}\\geq 0\\iff \\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$. Given (a), $\\lambda(C)\\geq 0\\iff B(C)/\\tau_{\\mathrm{ind}}\\leq 1\\iff|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$.\n\n\\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\\lambda_0\\,V_W(C)/(V_W(C)+\\sigma_\\varepsilon^2)$; the rank-one limit $V_W{\\to}V$ yields $\\tau_{\\mathrm{ind}}=\\lambda_0\\,V/(V+\\sigma_\\varepsilon^2)$. Both quantities carry $\\operatorname{sign}(\\lambda_0)$, establishing~(a). The ratio\n\\[\n  \\frac{B(C)}{\\tau_{\\mathrm{ind}}}\\;=\\;\\frac{V_W(C)\\,(V+\\sigma_\\varepsilon^2)}{V\\,(V_W(C)+\\sigma_\\varepsilon^2)}\n\\]\nis monotone increasing in $V_W(C)\\in[0,V]$ with range $[0,1]$ (its derivative in $V_W$ is $\\sigma_\\varepsilon^2(V+\\sigma_\\varepsilon^2)/[V(V_W+\\sigma_\\varepsilon^2)^2]>0$), establishing~(b). Hence $\\lambda(C)\\in[0,1]$ unconditionally.\n\n\\emph{General case.} Substituting $\\lambda(C)$ from~\\eqref{eq:lambda_def} into~\\eqref{eq:mediation} yields $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)=\\lambda(C)\\,\\tau_{\\mathrm{dir}}+(1{-}\\lambda(C))\\,\\tau_{\\mathrm{total}}$, so $\\lambda(C)\\in[0,1]$ iff $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{total}}$.\n\n\\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\\mathbb{E}[T\\mid A^*]=g(A)$, and FWL gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\tau_{\\mathrm{dir}}$, hence $B(I)=0$ and $\\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\\perp A$ so $\\mathbb{E}[T\\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\operatorname{Cov}(Y,T)/\\operatorname{Var}(T)=\\tau_{\\mathrm{total}}$, giving $B=\\tau_{\\mathrm{ind}}$ and $\\lambda=0$.\n\\end{proof}\n\n\\paragraph{Relation to the between-variance ratio.}\nA natural \\emph{diagnostic} closely related to $\\lambda(C)$ is the between-variance ratio\n\\begin{equation}\n\\label{eq:vb_ratio}\n  \\lambda_V(C) \\;:=\\; \\frac{V_B(C)}{V},\\qquad V_B(C)\\;=\\;\\operatorname{Var}\\!\\bigl(\\mathbb{E}[g(A)\\mid A^*]\\bigr),\\quad V\\;=\\;\\operatorname{Var}(g(A)),\n\\end{equation}\nwhich satisfies $\\lambda_V(C)\\in[0,1]$ \\emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\\lambda$ and $\\lambda_V$ agree at the endpoints and are related by\n\\[\n  1-\\lambda(C)\\;=\\;\\frac{V_W(C)\\,(V+\\sigma_\\varepsilon^2)}{V\\,(V_W(C)+\\sigma_\\varepsilon^2)}\\;=\\;\\bigl(1-\\lambda_V(C)\\bigr)\\cdot\\frac{V+\\sigma_\\varepsilon^2}{V_W(C)+\\sigma_\\varepsilon^2},\n\\]\nso they coincide in the limit $\\sigma_\\varepsilon^2\\gg V$. They generally differ for non-proportional $f$. We use $\\lambda$ throughout the main text because it parameterizes~\\eqref{eq:mediation} directly; $\\lambda_V$ remains a useful summary of the channel quality of $A^*$ as a proxy for $A$ (independent of the structural form of $f$).\n\n\\paragraph{Numerical verification.}\nFor each $K\\in\\{3,5,7\\}$ we draw $N{=}10{,}000$ configurations $(\\pi,g,\\sigma_\\varepsilon^2,C)$ with $\\pi\\sim\\operatorname{Dirichlet}(\\mathbf{1})$, $g\\sim\\mathcal{N}(0,I_K)$, $\\sigma_\\varepsilon^2\\sim\\operatorname{Uniform}(0.1,2)$, columns of $C\\sim\\operatorname{Dirichlet}(\\mathbf{1})$, and evaluate $\\lambda(C)$ from~\\eqref{eq:lambda_def} in two regimes for $f$:\n\\begin{itemize}\\itemsep0pt\n\\item \\textbf{Proportional} ($f=\\lambda_0\\,g$, $\\lambda_0\\sim\\mathcal{N}(0,1)\\!\\setminus\\!\\{0\\}$): $\\lambda(C)\\in[0,1]$ in \\emph{all} $30{,}000$ trials (pooled observed range $[1.2{\\times}10^{-5},\\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ therefore reduces to $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\n\\item \\textbf{Non-proportional} ($f\\sim\\mathcal{N}(0,I_K)$ drawn independently of $g$, restricted to $|\\tau_{\\mathrm{ind}}|\\geq 0.05$ to avoid the ill-conditioned regime where $\\lambda{=}1{-}B/\\tau_{\\mathrm{ind}}$ diverges): $\\lambda(C)$ exceeds $[0,1]$ in $\\sim15$--$17\\%$ of trials, illustrating that (a) and (b) are not automatic outside the proportional case.\n\\end{itemize}\nThe diagnostic $\\lambda_V(C)$ lies in $[0,1]$ across all $30{,}000$ trials irrespective of regime, as guaranteed by the law of total variance. The script and full results are in \\texttt{artifacts/verify\\_lambda\\_bound.py} and \\texttt{artifacts/verify\\_lambda\\_bound\\_results.json}.\n\n\\subsection{Collider Topology ($A$ = Collider)}\n\\label{app:collider}\n\n\\paragraph{Data-generating process.}\n$T\\to A\\leftarrow Y$, $T\\to Y$.\nThe treatment effect is unconfounded:\n\\begin{align*}\n  T &\\sim \\mathcal{N}(0,1),\\quad\n  Y = \\tau\\,T + \\varepsilon_Y,\\quad \\varepsilon_Y\\sim\\mathcal{N}(0,1),\\;\\varepsilon_Y\\perp T,\\\\\n  A\\mid T,Y &\\sim \\operatorname{Categorical}\\bigl(\\operatorname{softmax}(\\boldsymbol{\\delta}_T\\,T + \\boldsymbol{\\delta}_Y\\,Y)\\bigr).\n\\end{align*}\nThe collider $A$ is a common \\emph{effect} of $T$ and $Y$.\nThe no-control estimator (regressing $Y$ on $T$ alone) is consistent: $\\operatorname{plim}\\hat\\tau_{\\mathrm{nc}}=\\tau$.\nThe researcher erroneously controls for $A^*$, inducing Berkson's bias.\n\n\\paragraph{Bias decomposition.}\nUnlike confounding, $\\varepsilon_Y$ is not independent of $A$ (since $A$ depends on $Y=\\tau T+\\varepsilon_Y$), so Lemma~\\ref{lem:bias_decomp} does not apply directly.\nInstead, we derive the bias from the FWL identity~\\eqref{eq:fwl}.\nWriting $\\tilde{Y}=\\tau\\tilde{T}+(\\varepsilon_Y-\\mathbb{E}[\\varepsilon_Y\\mid A^*])$ and noting that $\\mathbb{E}[\\tilde{T}\\,\\varepsilon_Y]=\\mathbb{E}[\\operatorname{Cov}(T,\\varepsilon_Y\\mid A^*)]$ (since $T\\perp\\varepsilon_Y$ unconditionally):\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C) = \\tau + B(C),\\quad\n  B(C) = \\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,\\varepsilon_Y\\mid A^*)]}{\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]}.\n  \\label{eq:bias_col}\n\\end{equation}\nUnder non-differential misclassification ($A^*\\perp(T,\\varepsilon_Y)\\mid A$), define $g(k)=\\mathbb{E}[T\\mid A{=}k]$ and $h(k)=\\mathbb{E}[\\varepsilon_Y\\mid A{=}k]$.\nBy the tower property, $\\mathbb{E}[T\\mid A^*]=\\mathbb{E}[g(A)\\mid A^*]$ and $\\mathbb{E}[\\varepsilon_Y\\mid A^*]=\\mathbb{E}[h(A)\\mid A^*]$.\nSince $\\operatorname{Cov}(T,\\varepsilon_Y)=0$, the law of total covariance gives:\n\\[\n  B(C) = \\frac{-\\operatorname{Cov}\\bigl(\\mathbb{E}[g(A)\\mid A^*],\\;\\mathbb{E}[h(A)\\mid A^*]\\bigr)}{\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]}.\n\\]\n\n\\paragraph{Endpoint analysis.}\nAt $C=I$ ($A^*{=}A$):\n$B(I) = -\\operatorname{Cov}(g(A),h(A))\\,/\\,\\mathbb{E}[\\operatorname{Var}(T\\mid A)] = B_{\\mathrm{Berkson}}$,\nthe full Berkson's bias from conditioning on the collider.\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ ($A^*\\perp A$):\n$\\mathbb{E}[g(A)\\mid A^*]$ and $\\mathbb{E}[h(A)\\mid A^*]$ are constant, so $B=0$ and $\\operatorname{plim}\\hat\\tau=\\tau$.\n\nThis is the structural reverse of confounding: misclassification attenuates the collider-induced bias toward zero, rather than growing bias from zero toward $B_{\\mathrm{OV}}$.\n\n\\begin{proposition}[Collider sign preservation --- proportional case]\n\\label{prop:col_prop}\nIf $h(A)=\\lambda\\,g(A)$ for some constant $\\lambda$, then $|B(C)|\\leq|B(I)|$ for all column-stochastic $C$, and $B(C)$ has the same sign as $B(I)$.\nConsequently, $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau)=\\operatorname{sign}(\\tau)$ whenever $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau+B_{\\mathrm{Berkson}})$.\n\\end{proposition}\n\n\\begin{proof}\nWhen $h=\\lambda g$, the numerator becomes $-\\lambda\\,\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])$ and the denominator is $\\operatorname{Var}(T)-\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])$.\nLet $V^*=\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])\\in[0,V_g]$ where $V_g=\\operatorname{Var}(g(A))$.\nThen\n\\[\n  |B(C)| = |\\lambda|\\,\\frac{V^*}{\\operatorname{Var}(T)-V^*}.\n\\]\nThe function $x\\mapsto x/(a-x)$ is increasing on $[0,a)$.\nWith $a=\\operatorname{Var}(T)>V_g\\geq V^*$:\n$|B(C)|\\leq|\\lambda|\\,V_g/(\\operatorname{Var}(T)-V_g)=|B(I)|$.\nAt $V^*{=}0$ (uniform $C$): $B{=}0$.  At $V^*{=}V_g$ ($C{=}I$): $B{=}B(I)$.\n\\end{proof}\n\n\\begin{proposition}[Collider sign preservation --- general case]\n\\label{prop:col_gen}\nDefine\n\\begin{equation}\n  \\bar{B}_{\\mathrm{col}} = \\frac{\\sqrt{\\operatorname{Var}(g(A))\\,\\operatorname{Var}(h(A))}}{\\mathbb{E}[\\operatorname{Var}(T\\mid A)]}.\n  \\label{eq:bbar_col}\n\\end{equation}\nIf $|\\tau|>\\bar{B}_{\\mathrm{col}}$, then $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau(C))=\\operatorname{sign}(\\tau)$ for all column-stochastic $C$.\n\\end{proposition}\n\n\\begin{proof}\n\\emph{Step~1: Bound the numerator.}\nBy Cauchy--Schwarz:\n$|\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[h\\mid A^*])|\\leq\\sqrt{\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])\\,\\operatorname{Var}(\\mathbb{E}[h\\mid A^*])}$.\nSince conditional expectation reduces variance: $\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])\\leq\\operatorname{Var}(g(A))$ and likewise for $h$.\n\n\\emph{Step~2: Bound the denominator.}\n$\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]=\\operatorname{Var}(T)-\\operatorname{Var}(\\mathbb{E}[T\\mid A^*])\\geq\\operatorname{Var}(T)-\\operatorname{Var}(g(A))=\\mathbb{E}[\\operatorname{Var}(T\\mid A)]$.\n\n\\emph{Step~3: Conclude.}\n$|B(C)|\\leq\\sqrt{\\operatorname{Var}(g)\\,\\operatorname{Var}(h)}\\,/\\,\\mathbb{E}[\\operatorname{Var}(T\\mid A)]=\\bar{B}_{\\mathrm{col}}$.\nWhen $|\\tau|>\\bar{B}_{\\mathrm{col}}$, the bias cannot overwhelm $\\tau$.\n\\end{proof}\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\tau{=}1.0$, $\\boldsymbol{\\delta}_T{=}(0,\\,0.5,\\,{-}0.3)$, $\\boldsymbol{\\delta}_Y{=}(0,\\,0.8,\\,0.6)$, from $5{\\times}10^6$-sample Monte Carlo:\n\\begin{align*}\n  \\operatorname{Var}(g(A)) &= 0.187,\\quad\n  \\operatorname{Var}(h(A)) = 0.076,\\quad\n  \\mathbb{E}[\\operatorname{Var}(T\\mid A)] = 0.813,\\\\\n  \\bar{B}_{\\mathrm{col}} &= \\sqrt{0.187\\times 0.076}\\;/\\;0.813 = 0.147.\n\\end{align*}\nSince $|\\tau|{=}1.0\\gg\\bar{B}_{\\mathrm{col}}{=}0.147$, Proposition~\\ref{prop:col_gen} guarantees sign preservation.\nAdditionally, $B_{\\mathrm{Berkson}}{=}{-}0.114$, giving $\\tau+B_{\\mathrm{Berkson}}{=}0.886{>}0$.\nVerified across $100{,}000$ random column-stochastic $C$: $\\tau_{\\mathrm{sign\\,flip}}{=}0\\%$, and $|B(C)|\\leq|B_{\\mathrm{Berkson}}|$ in all cases.\n\n\\subsection{Front-door Topology ($A$ = Mediator under Confounding)}\n\\label{app:frontdoor}\n\n\\paragraph{Data-generating process.}\n$T\\to A\\to Y$, $U\\to T$, $U\\to Y$.\nAn unobserved confounder $U$ affects both treatment and outcome:\n\\begin{align*}\n  U &\\sim \\mathcal{N}(0,1),\\quad\n  T = \\alpha_U\\,U + \\eta,\\quad \\eta\\sim\\mathcal{N}(0,1),\\;\\eta\\perp U,\\\\\n  A\\mid T &\\sim \\operatorname{Categorical}\\bigl(\\operatorname{softmax}(\\boldsymbol{\\gamma}+\\boldsymbol{\\delta}\\,T)\\bigr),\\\\\n  Y &= f(A) + \\lambda\\,U + \\varepsilon_Y,\\quad \\varepsilon_Y\\perp(T,A,U).\n\\end{align*}\nThere is no direct $T{\\to}Y$ edge; the causal effect of $T$ on $Y$ operates entirely through $A$.\nThe researcher controls for $A^*$ in $Y\\sim 1+T+D_1^*+\\cdots+D_{K-1}^*$.\n\n\\paragraph{Bias decomposition.}\nSince the direct effect is zero, the FWL coefficient on $T$ captures only bias:\n\\[\n  \\operatorname{plim}\\hat\\tau(C) = \\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,Y\\mid A^*)]}{\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]}.\n\\]\nSubstituting $Y=f(A)+\\lambda U+\\varepsilon_Y$ and using $\\varepsilon_Y\\perp(T,A,A^*)$:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C)\n  = \\underbrace{\\frac{\\lambda\\,\\alpha_U}{\\operatorname{Var}(T)}}_{\\text{confounding (constant)}}\n  \\;+\\; \\underbrace{\\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)]}{D(C)}}_{\\displaystyle B_{\\mathrm{med}}(C)},\n  \\label{eq:fd_decomp}\n\\end{equation}\nwhere $D(C)=\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]$.\n\n\\begin{proof}[Derivation of~\\eqref{eq:fd_decomp}]\nExpand the numerator as\n$\\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)] + \\lambda\\,\\mathbb{E}[\\operatorname{Cov}(T,U\\mid A^*)]$.\nFor the confounding term: since $T=\\alpha_U U+\\eta$ with $(U,\\eta)$ jointly Gaussian, the regression residual $\\xi=U-\\frac{\\alpha_U}{\\operatorname{Var}(T)}T$ satisfies $\\xi\\perp T$.\nBecause $A$ is a function of $T$ (plus independent softmax noise) and $A^*$ is a function of $A$ (plus independent misclassification noise), $\\xi\\perp(T,A,A^*)$.\nTherefore\n\\[\n  \\operatorname{Cov}(T,U\\mid A^*{=}j)\n  = \\frac{\\alpha_U}{\\operatorname{Var}(T)}\\,\\operatorname{Var}(T\\mid A^*{=}j)\n  \\quad\\forall\\;j,\n\\]\nand $\\lambda\\,\\mathbb{E}[\\operatorname{Cov}(T,U\\mid A^*)]=\\frac{\\lambda\\alpha_U}{\\operatorname{Var}(T)}\\,D(C)$, yielding the constant first term after division by $D(C)$.\n\\end{proof}\n\nThis decomposition reveals that \\emph{misclassification does not affect the confounding component}.\nThe confusion matrix $C$ modulates only the mediation-type leakage $B_{\\mathrm{med}}(C)$, which has the same structure as in~§\\ref{app:mediation}.\n\n\\paragraph{Endpoint analysis.}\nAt $C=I$: $B_{\\mathrm{med}}(I)=0$ (controlling $A$ blocks the $T\\to A\\to Y$ path), and $\\operatorname{plim}\\hat\\tau(I)=\\lambda\\alpha_U/\\operatorname{Var}(T)$ (pure confounding residual).\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$: $B_{\\mathrm{med}}=\\operatorname{Cov}(T,f(A))/\\operatorname{Var}(T)$, and $\\operatorname{plim}\\hat\\tau_{\\mathrm{nc}}=[\\operatorname{Cov}(T,f(A))+\\lambda\\alpha_U]/\\operatorname{Var}(T)$, the naive regression coefficient with no controls.\n\n\\paragraph{Numerical Verification (Front-door sign preservation).}\n\\label{find:fd_sign}\nSince $B_{\\mathrm{med}}(C)$ has the same structure as the mediation bias (§\\ref{app:mediation})---interpolating between $0$ at $C{=}I$ and $\\operatorname{Cov}(T,f(A))/\\operatorname{Var}(T)$ at $C$ uniform---sign preservation holds whenever the two endpoints have the same sign:\n\\[\n  \\operatorname{sign}\\!\\bigl(\\lambda\\alpha_U\\bigr)\n  = \\operatorname{sign}\\!\\bigl(\\lambda\\alpha_U + \\operatorname{Cov}(T,f(A))\\bigr).\n\\]\nThis result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$.\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\alpha_U{=}1.0$, $\\lambda{=}1.0$, $\\boldsymbol{\\beta}{=}(0,1.0,{-}0.5)$, $\\boldsymbol{\\gamma}{=}(0,0.5,{-}0.3)$, $\\boldsymbol{\\delta}{=}(0,1.0,{-}0.8)$:\n\\begin{align*}\n  \\lambda\\alpha_U/\\operatorname{Var}(T) &= 1.0\\times 1.0\\,/\\,2.0 = 0.500,\\\\\n  \\operatorname{Cov}(T,f(A))/\\operatorname{Var}(T) &= 0.594\\,/\\,2.0 = 0.297.\n\\end{align*}\nBoth components are positive, so $\\operatorname{plim}\\hat\\tau(C)\\in[0.500,\\,0.797]>0$ for all $C$.\n\n\\subsection{Exposure Topology: Sign Reversal Counterexample}\n\\label{app:exposure}\n\n\\begin{proposition}[Exposure sign reversal]\n\\label{prop:exp_counter}\nFor $K{=}3$ with $A$ as the treatment variable, there exist a marginal distribution $\\mathbf{p}$, treatment effects $\\boldsymbol{\\beta}$, and a column-stochastic $C$ with $C_{kk}>0.5$ for all $k$, such that $\\operatorname{sign}(\\operatorname{plim}\\hat\\beta_1)\\neq\\operatorname{sign}(\\beta_1)$.\n\\end{proposition}\n\n\\begin{proof}[Construction]\nConsider the exposure DGP $Y = \\beta_1 D_1 + \\beta_2 D_2 + \\varepsilon_Y$ with:\n\\begin{itemize}\n  \\item Uniform prior: $\\mathbf{p}=(1/3,\\,1/3,\\,1/3)$.\n  \\item True effects: $\\beta_1=1$,\\; $\\beta_2=-10$.\n\\end{itemize}\nChoose the confusion matrix\n\\[\n  C = \\begin{pmatrix}\n    0.60 & 0.10 & 0.10\\\\\n    0.10 & 0.60 & 0.39\\\\\n    0.30 & 0.30 & 0.51\n  \\end{pmatrix},\\qquad\n  C_{kk}\\in\\{0.60,\\,0.60,\\,0.51\\},\\;\\text{all}>0.5.\n\\]\nColumn sums are $1$ (verifiable by inspection).\n\nThe OLS estimator regresses $Y$ on $(1,D_1^*,D_2^*)$.\nThe plim of $\\hat\\beta_j$ equals $\\mathbb{E}[Y\\mid A^*{=}j]-\\mathbb{E}[Y\\mid A^*{=}0]$, where\n\\[\n  \\mathbb{E}[Y\\mid A^*{=}j] = \\sum_{k=0}^{2} P(A{=}k\\mid A^*{=}j)\\,\\beta_k\n  = \\sum_{k=1}^{2}\\frac{C_{jk}\\,p_k}{q_j}\\,\\beta_k.\n\\]\n\n\\emph{Marginal distribution of $A^*$:}\n\\begin{align*}\n  q_0 &= \\tfrac{1}{3}(0.60+0.10+0.10)=0.267,\\\\\n  q_1 &= \\tfrac{1}{3}(0.10+0.60+0.39)=0.363,\\\\\n  q_2 &= \\tfrac{1}{3}(0.30+0.30+0.51)=0.370.\n\\end{align*}\n\n\\emph{Conditional means:}\n\\begin{align*}\n  \\mathbb{E}[Y\\mid A^*{=}0]\n  &= \\frac{0.10\\times\\tfrac{1}{3}\\times 1 + 0.10\\times\\tfrac{1}{3}\\times({-}10)}{0.267}\n  = \\frac{0.0333-0.3333}{0.267} = -1.125,\\\\[4pt]\n  \\mathbb{E}[Y\\mid A^*{=}1]\n  &= \\frac{0.60\\times\\tfrac{1}{3}\\times 1 + 0.39\\times\\tfrac{1}{3}\\times({-}10)}{0.363}\n  = \\frac{0.200-1.300}{0.363} = -3.028,\\\\[4pt]\n  \\mathbb{E}[Y\\mid A^*{=}2]\n  &= \\frac{0.30\\times\\tfrac{1}{3}\\times 1 + 0.51\\times\\tfrac{1}{3}\\times({-}10)}{0.370}\n  = \\frac{0.100-1.700}{0.370} = -4.324.\n\\end{align*}\n\n\\emph{Estimated coefficient:}\n\\[\n  \\operatorname{plim}\\hat\\beta_1 = \\mathbb{E}[Y\\mid A^*{=}1]-\\mathbb{E}[Y\\mid A^*{=}0]\n  = -3.028-(-1.125) = \\mathbf{-1.903}.\n\\]\nThe true $\\beta_1=+1>0$ but $\\operatorname{plim}\\hat\\beta_1=-1.903<0$: \\textbf{sign reversal}.\n\n\\emph{Mechanism.}\nThe large off-diagonal entry $C_{12}=0.39$ (probability of classifying true category~2 as $A^*{=}1$) routes substantial probability mass from category~2 ($\\beta_2=-10$) into the $A^*{=}1$ bin.\nDespite $C_{11}=0.60>0.5$, the contamination from the strongly negative $\\beta_2$ overwhelms the positive $\\beta_1$, reversing the sign of the estimated effect for category~1.\nThis failure mode is structurally impossible at $K{=}2$: a $2{\\times}2$ column-stochastic matrix with $C_{kk}>0.5$ has the form $C=\\bigl(\\begin{smallmatrix}a&1{-}b\\\\1{-}a&b\\end{smallmatrix}\\bigr)$ with $a,b>0.5$, and the single coefficient $\\hat\\beta_1$ is a positive-weighted average of $\\beta_1$, preserving sign.\nFor $K{\\geq}3$, the additional degrees of freedom in $C$ permit cross-contamination between categories with opposite-sign effects.\n\\end{proof}\n\n\\subsection{Summary of Conditions}\n\\label{app:conditions}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Sufficient condition} & \\textbf{Status} & \\textbf{Paper DGP} \\\\\n\\midrule\nConfounding & $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau{+}B_{\\mathrm{OV}})$ & Proved & $\\checkmark$ ($2.0$ vs $2.3$)\\\\\nCollider & $|\\tau|>\\bar{B}_{\\mathrm{col}}$ (Prop.~\\ref{prop:col_gen}) & Proved & $\\checkmark$ ($1.0$ vs $0.15$)\\\\\n\\midrule\nMediation & $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$ & Empirical & $\\checkmark$ ($0.5$ vs $0.85$)\\\\\nM-bias & Bias is attenuating (toward $\\tau$) & Empirical & $\\checkmark$ \\\\\nFront-door & $\\operatorname{sign}(\\lambda\\alpha_U)=\\operatorname{sign}(\\lambda\\alpha_U{+}\\operatorname{Cov}(T,f))$ & Empirical & $\\checkmark$ ($0.50$ vs $0.80$)\\\\\n\\midrule\nExposure & Not guaranteed for $K\\geq 3$ & Counterex. & See §\\ref{app:exposure} \\\\\nIV & Not guaranteed (denominator instability) & --- & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Sufficient conditions for sign preservation under non-differential misclassification.\n``Proved'' = algebraic proof via Cauchy--Schwarz (confounding) or Berkson attenuation (collider).\n``Empirical'' = verified across 100{,}000 random column-stochastic matrices with zero violations; analytic proof for general $K$ remains open.\nAll conditions are on DGP parameters (not on $C$): once satisfied, sign preservation holds for all column-stochastic $C$ with $C_{kk}>0$.}\n\\label{tab:sign_conditions}\n\\end{table}\n\n\\paragraph{Structural argument for M-bias topology.}\n\\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.\nMisclassification of $A$ weakens the statistical association along this backdoor path, reducing the spurious correlation rather than amplifying it.\nThe bias therefore interpolates between the full M-bias (perfect classification, $\\delta{=}0$) and zero (no classification information, $\\delta{\\to}\\delta_{\\max}$), monotonically non-increasing in $\\delta$.\n\n\\paragraph{Remark.}\nThe sign preservation conditions for confounding, mediation, collider, and front-door are conditions on the DGP parameters (the relative strength of the causal effect versus the confounding, indirect, or collider-induced bias), not on the confusion matrix $C$.\nOnce the condition is satisfied, sign preservation holds for \\emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.\nConversely, if the condition fails (i.e., the omitted-variable or total-effect estimate has the opposite sign from $\\tau$), then there exist confusion matrices that produce sign reversal.\nFor the DGP parameters used throughout our experiments, the conditions are comfortably satisfied.\nThe sign-alignment condition is violated when the confounder has opposing effects on treatment and outcome (e.g., $\\gamma_A > 0$ on $T$ but $\\gamma_A < 0$ on $Y$), producing $\\operatorname{sign}(\\tau) \\neq \\operatorname{sign}(\\tau_{\\mathrm{OV}})$. In applied settings, such opposing effects are uncommon when the analyst adjusts for $A$ precisely because they believe it confounds the $T$--$Y$ relationship in a consistent direction. When the condition fails, sign reversal becomes possible under sufficient misclassification, though this represents a pathological DGP where adjustment itself may be questionable.\n\n\\section{Supplementary Tables, Figures, and Algorithm}\n\\label{app:supplementary}\n\n\\subsection{Binarization Collapse}\n\\label{app:binarization}\n\nCollapsing $K$-class annotations to binary before analysis discards multi-class error structure. We quantify ``binarization collapse'' as $\\Delta = |\\text{bias}_{K} - \\text{bias}_{K \\to 2}|$.\n\nFor $K{=}3$, binarization introduces additional bias varying 154$\\times$ across topologies: from $\\bar{\\Delta}{=}0.006$ (M-bias) to $\\bar{\\Delta}{=}0.926$ (IV). Exposure and IV also introduce sign flips during binarization (14\\% and 17.5\\%), a phenomenon absent in the other topologies (Figure~\\ref{fig:binarization}).\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\textwidth]{fig3_asv_ranking.pdf}\n\\caption{ASV sensitivity ranking across topologies. Three ASV types (magnitude, significance, sign-flip) reveal a topology-dependent vulnerability spectrum from IV (maximally fragile, 52.6\\% sign reversal; sign-flip ASV $= 1.1$--$6.7$) to M-bias (immune, ASV $= \\infty$).}\n\\label{fig:asv_ranking}\n\\end{figure*}\n\n\\begin{table}[h]\n\\centering\n\\caption{ASV type applicability and sensitivity across DAG topologies. Magnitude ASV at $\\tau{=}0.5$, 10\\% threshold. Power at $\\tau{=}0.05$ significance filter. ---: not applicable.}\n\\label{tab:asv_grid}\n\\small\n\\begin{tabular}{lcccl}\n\\toprule\n\\textbf{Topology} & \\textbf{Mag. ASV} & \\textbf{Signif.} & \\textbf{Sign-flip} & \\textbf{Rank} \\\\\n\\midrule\nIV & 0.101--0.607 & 0\\% & 1.1--6.7 & 1 (fragile) \\\\\nFront-door & 0.064--0.387 & 100\\% & --- & 2 \\\\\nConfounding & 0.081--0.487 & 100\\% & --- & 3 \\\\\nMediation & 0.076--0.454 & 0\\% & --- & 4 \\\\\nCollider & 0.338--2.028 & 0\\% & --- & 5 \\\\\nM-bias & $\\infty$ & 96--100\\% & --- & 6 (immune) \\\\\nExposure & --- & --- & 83.4\\%$^*$ & --- \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize $^*$Fraction of $C_0$ with $\\tau_{\\text{sign\\_flip}} < 1$. Exposure uses sign-flip ASV exclusively.}\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig7_dirichlet_overlay.pdf}\n\\caption{Empirical LLM confusion matrices overlaid on theoretical violation-rate curves (exposure, left; IV, right). Theoretical curves are derived from $K{=}3$ Dirichlet random matrices; empirical points are positioned at their minimum diagonal entry. Markers denote datasets (circles: HumAID $K{=}10$; squares: VAST $K{=}3$; triangles: CivilComments $K{=}2$).}\n\\label{fig:dirichlet_overlay}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig4_binarization.pdf}\n\\caption{Binarization collapse $\\Delta$ across topologies. Collapsing $K{=}3$ annotations to binary introduces additional bias varying 154$\\times$ from M-bias (0.006) to IV (0.926).}\n\\label{fig:binarization}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig6_asv_heatmap.pdf}\n\\caption{ASV magnitude ranges across topologies for HumAID ($K{=}10$). Left: magnitude ASV ($\\delta^*$) range across 8 LLM configurations; lower values indicate greater fragility. ``Safe'' topologies never exceed the 10\\% bias threshold. Right: percentage of configurations flagged as ASV-unsafe.}\n\\label{fig:asv_heatmap}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{RMSE reduction (\\%) by correction method and DAG topology (mean across 6 error structures, $N_{\\text{sim}}{=}1{,}000$). Positive = reduced RMSE; negative = increased RMSE. Naive/MLA show 0.0\\% for FWL-invariant topologies because $C^{-1}$ cannot change the $T$ coefficient. \\textbf{Bold}: best method per topology; \\underline{underline}: best gold-free method.}\n\\label{tab:correction}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Naive} & \\textbf{MLA} & \\textbf{DSL} & \\textbf{SIMEX} & \\textbf{PPI++} \\\\\n\\midrule\nConfounding & 0.0 & 0.0 & \\underline{48.0} & 35.1 & \\textbf{83.2} \\\\\nMediation & 0.0 & 0.0 & \\underline{52.9} & 39.1 & \\textbf{54.1} \\\\\nCollider & 0.0 & 0.0 & $-$92.6 & \\underline{31.8} & \\textbf{50.5} \\\\\nM-bias & 0.0 & 0.0 & $-$267 & \\textbf{\\underline{0.1}} & $-$88.0 \\\\\n\\midrule\nFront-door & $-$52.7 & $-$111.5 & \\underline{$-$29.0} & $-$62.4 & \\textbf{74.1} \\\\\nExposure & $-$44.8 & $-$89.0 & $-$59.5 & \\underline{$-$9.8} & \\textbf{75.5} \\\\\nIV & $-$40.4 & $-$58.7 & $-$206.1 & \\underline{59.4} & \\textbf{79.4} \\\\\n\\midrule\nGrand mean & $-$19.7 & $-$37.0 & $-$79.0 & 13.3 & \\textbf{47.0} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Error structures used in correction experiments.}\nThe six confusion matrix structures used for Table~\\ref{tab:correction} are:\n(1)~\\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;\n(2)~\\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;\n(3)~\\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;\n(4)~\\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);\n(5)~\\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;\n(6)~\\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.\nAll are column-stochastic with $K{=}3$. Results are averaged across all six structures.\n\n\\begin{algorithm}[h]\n\\caption{Correction method selection for LLM-annotated causal inference. Assumes linear structural equations; FWL-based routing may not apply under nonlinear models (see Appendix~\\ref{sec:logistic_dgp}).}\n\\label{alg:correction}",
      "numLines": 400,
      "startLine": 400,
      "totalLines": 1066
    }
  },
  "sourceToolAssistantUUID": "51c40010-83f4-4e7b-85a7-e1207a22013d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 43_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "2048edc4-cc6c-4894-98e2-0b45f378636a",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Assistant

_source line 44 · 2026-05-22T16:55:22.660Z_

<details><summary>Logged reasoning block</summary>

```text
Let me continue reading the rest of the appendix.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2048edc4-cc6c-4894-98e2-0b45f378636a",
  "isSidechain": false,
  "requestId": "req_011CbHxXriF5XARXfiYLPa5m",
  "type": "assistant",
  "uuid": "2b4faef3-2fa3-4978-b29b-ec0c0f274e07",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019RW979d7ckMeVxDSR6DYsa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 24960,
      "cache_read_input_tokens": 43650,
      "output_tokens": 152,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 24960,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 152,
          "cache_read_input_tokens": 43650,
          "cache_creation_input_tokens": 24960,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 24960
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

_source line 45 · 2026-05-22T16:55:24.566Z_

<details open><summary>🔧 Tool call — Read · `toolu_01B5o8HgT4B14fKrBbD3DsSf`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 800,
  "limit": 400
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2b4faef3-2fa3-4978-b29b-ec0c0f274e07",
  "isSidechain": false,
  "requestId": "req_011CbHxXriF5XARXfiYLPa5m",
  "type": "assistant",
  "uuid": "9a21eb4c-63de-4ce7-97c5-c734911953c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019RW979d7ckMeVxDSR6DYsa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 24960,
      "cache_read_input_tokens": 43650,
      "output_tokens": 152,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 24960,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 152,
          "cache_read_input_tokens": 43650,
          "cache_creation_input_tokens": 24960,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 24960
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

_source line 46 · 2026-05-22T16:55:24.636Z_

<details><summary>↩ Tool result · `toolu_01B5o8HgT4B14fKrBbD3DsSf`</summary>

```text
800	\small
801	\begin{algorithmic}[1]
802	\REQUIRE DAG topology $\mathcal{T}$, gold-label availability $G \in \{\textsc{yes}, \textsc{no}\}$
803	\ENSURE Recommended method $M$, risk level $R$
804	\STATE
805	\STATE \textbf{Step 1: Assess risk level}
806	\IF{$\mathcal{T} \in \{\text{M-bias}\}$}
807	    \STATE $R \gets \textsc{Low}$ \COMMENT{$|\text{bias}| < 0.04$ for all $C$}
808	\ELSIF{$\mathcal{T} \in \{\text{Conf., Med., Coll., Front-door}\}$}
809	    \STATE $R \gets \textsc{Medium}$ \COMMENT{bounded bias, no sign reversal}
810	\ELSE
811	    \STATE $R \gets \textsc{High}$ \COMMENT{Exposure, IV: sign reversal 83.4\% / 52.6\%}
812	\ENDIF
813	\STATE
814	\STATE \textbf{Step 2: Select correction method}
815	\IF{$G = \textsc{yes}$}
816	    \IF{$\mathcal{T} = \text{M-bias}$}
817	        \STATE $M \gets \textsc{None}$ \COMMENT{PPI++ RMSE red.\ $-$88.0\%; no correction preferred}
818	    \ELSE
819	        \STATE $M \gets \text{PPI++}$ \COMMENT{47.0\% RMSE red., 96.8\% coverage}
820	    \ENDIF
821	\ELSE
822	    \STATE \COMMENT{no gold labels}
823	    \IF{$\mathcal{T} \in \{\text{Confounding, Mediation}\}$}
824	        \STATE $M \gets \text{DSL}$ \COMMENT{48.0\% / 52.9\% RMSE reduction}
825	    \ELSIF{$\mathcal{T} = \text{IV}$}
826	        \STATE $M \gets \text{MC-SIMEX}$ \COMMENT{59.4\% RMSE reduction}
827	    \ELSIF{$\mathcal{T} \in \{\text{Collider, M-bias}\}$}
828	        \STATE $M \gets \text{MC-SIMEX}$ \COMMENT{31.8\% / 0.1\% RMSE reduction}
829	    \ELSE
830	        \STATE $M \gets \emptyset$; flag: acquire gold labels \COMMENT{no reliable gold-free method}
831	    \ENDIF
832	\ENDIF
833	\STATE
834	\STATE \textbf{Step 3: FWL invariance warning}
835	\IF{$\mathcal{T} \in \{\text{Conf., Med., Coll., M-bias}\}$}
836	    \STATE Skip Naive plug-in and MLA \COMMENT{0\% bias red.\ on $T$ coeff.}
837	\ENDIF
838	\RETURN $(M, R)$
839	\end{algorithmic}
840	\end{algorithm}
841	
842	\subsection{Proof of FWL Invariance}
843	\label{app:fwl_proof}
844	
845	For the four topologies where $A$ enters as a covariate (confounding, mediation, collider, M-bias), the regression is $Y = \tau T + \boldsymbol{\gamma}^\top \mathbf{D}^* + \varepsilon$, where $\mathbf{D}^*$ is the $N \times (K{-}1)$ dummy matrix for $A^*$. Any matrix-based correction replaces $\mathbf{D}^*$ with $\tilde{\mathbf{D}} = \mathbf{D}^* M$ for some invertible $(K{-}1) \times (K{-}1)$ matrix $M$ (e.g., $M = C^{-1}$ for plug-in, or $M = (C^\top C)^{-1} C^\top$ for MLE). By the Frisch--Waugh--Lovell theorem~\cite{lovell1963}, $\hat{\tau}$ depends only on the residual of $T$ projected off $\operatorname{col}(\mathbf{D}^*)$. Since $\operatorname{col}(\mathbf{D}^* M) = \operatorname{col}(\mathbf{D}^*)$ for invertible $M$, the projection is unchanged and $\hat{\tau}(\tilde{\mathbf{D}}) = \hat{\tau}(\mathbf{D}^*)$ exactly. SIMEX adds noise $\mathbf{D}^*_{\text{sim}} = \mathbf{D}^* + \lambda \mathbf{E}$; when $\mathbf{E}$ is generated from the same column space, the extrapolation to $\lambda = -1$ converges to a column-space-equivalent transformation, yielding 0\% bias reduction empirically.
846	
847	\subsection{Applied Illustration: ClinicalBERT Case Study}
848	\label{app:case_study}
849	
850	To demonstrate the framework's end-to-end utility, we apply it retrospectively to \citet{lee_wood_doughty2024}, who use ClinicalBERT to classify patient smoking status ($K{=}4$: never, past, current, unknown) from clinical notes and control for this predicted confounder when estimating the causal effect of echocardiography on mortality in 4{,}735 MIMIC-III sepsis patients.
851	Our taxonomy identifies this as a \emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.
852	Three conclusions follow directly.
853	First, the zero sign-flip guarantee for confounding (Table~\ref{tab:taxonomy}) ensures that the estimated protective effect (OR~$= 0.89$) cannot reverse direction due to annotation error---a reassurance unavailable without topology-specific analysis.
854	Second, the FWL invariance result implies that any correction reducing to $C^{-1}$ applied to the dummy-coded confounder achieves exactly 0\% bias reduction for the treatment coefficient; naive plug-in is provably futile here.
855	Third, our correction guidance ranks PPI++ (83.2\% RMSE reduction for confounding) above MC-SIMEX (35.1\%) when gold labels are available---a concrete recommendation the original study lacked.
856	This example illustrates the intended workflow: DAG identification $\to$ topology-specific guarantees $\to$ correction method selection.
857	
858	\subsection{IV Wald Estimator: Diagonal-Dominance Subspaces}
859	\label{sec:iv_dirichlet_subspace}
860	
861	Section~\ref{sec:taxonomy_results} reports a 52.6\% Wald sign-flip rate
862	over the full Dirichlet$(1,1,1)$ prior. Because realistic LLM confusion
863	matrices are diagonal-dominant, we replicate the exposure-DAG stratification
864	for the IV topology, restricting the sample
865	space to $\{C : \min_k C_{kk} \geq d\}$ for $d \in \{0, 0.5, 0.7, 0.9\}$
866	(100{,}000 random matrices per threshold).
867	
868	\begin{table}[h]
869	\centering
870	\caption{IV Wald estimator bias by minimum-diagonal subspace ($K{=}3$, $\tau_{\text{true}}{=}1.41$).
871	Rates over 100{,}000 Dirichlet-truncated random $C$ per threshold.}
872	\label{tab:iv_dirichlet_subspace}
873	\small
874	\begin{tabular}{lcccc}
875	\toprule
876	\textbf{Subspace} & \textbf{Violation} & \textbf{Sign Flip} & \textbf{Amplif.} & \textbf{Worst} \\
877	\midrule
878	Full           & 100.0\% & 51.7\% & 48.3\% & $10^{5}\!\times$ \\
879	$d \geq 0.5$   & 100.0\% & 0.0\%  & 100.0\% & $28.6\times$ \\
880	$d \geq 0.7$   & 100.0\% & 0.0\%  & 100.0\% & $2.4\times$ \\
881	$d \geq 0.9$   & 100.0\% & 0.0\%  & 100.0\% & $1.2\times$ \\
882	\bottomrule
883	\end{tabular}
884	\end{table}
885	
886	The contrast with exposure is instructive: at $d{\geq}0.7$, exposure violation drops to 13.7\% (sign reversal 2.1\%, amplification 11.7\%), while IV maintains 100\% violation with pure amplification. IV sign reversal is entirely driven by pathological (near-random) confusion matrices where the Wald denominator crosses zero; diagonal dominance prevents this crossing but cannot prevent amplification. Even at $d{\geq}0.9$, the Wald estimator inflates $|\tau|$ by up to $1.24\times$ with probability~1.
887	
888	\subsection{Non-Differential Assumption Stress Test}
889	\label{sec:nondiff_stress}
890	
891	Our main analysis assumes non-differential misclassification: the confusion matrix $C$ does not depend on the outcome $Y$. To assess sensitivity to violations of this assumption, we conduct a stress test on the exposure topology ($K{=}3$, $\min_k C_{kk} \geq 0.7$, 10{,}000 random matrices per $\varepsilon$). For each base matrix $C_0$, observations with $Y > \text{median}(Y)$ are misclassified using a perturbed matrix $\tilde{C} = \text{renormalize}(C_0 + \varepsilon \cdot \Delta)$ where $\Delta_{jk} \sim \text{Uniform}(-1,1)$ for $j \neq k$, while observations with $Y \leq \text{median}(Y)$ retain $C_0$.
892	
893	\begin{table}[h]
894	\centering
895	\small
896	\caption{Effect of differential misclassification on bias violation rates (exposure DAG, $K{=}3$, $\min_k C_{kk} \geq 0.7$, $N{=}50{,}000$ MC samples per trial).}
897	\label{tab:nondiff_stress}
898	\begin{tabular}{cccc}
899	\toprule
900	$\varepsilon$ & Sign-Flip (\%) & Amplification (\%) & Any Violation (\%) \\
901	\midrule
902	0.00 & 2.0 & 11.5 & 13.3 \\
903	0.01 & 2.4 & 12.4 & 14.7 \\
904	0.05 & 2.8 & 13.0 & 15.7 \\
905	0.10 & 4.5 & 16.7 & 20.9 \\
906	\bottomrule
907	\end{tabular}
908	\end{table}
909	
910	The $\varepsilon{=}0$ baseline (13.3\% violation) closely matches the analytical result (13.7\%) from Section~\ref{sec:taxonomy_results}. Even at $\varepsilon{=}0.10$---a substantial departure from non-differential error---the violation rate increases by only 7.6 percentage points. Small departures ($\varepsilon \leq 0.05$) change rates by fewer than 3 percentage points, suggesting that our main results are moderately robust to mild violations of the non-differential assumption.
911	
912	\paragraph{Extended stress test.}
913	An extended stress test across 96 configurations (4 topologies $\times$ 2 $K$ $\times$ 3 CM qualities $\times$ 4 $\varepsilon$, 100 MC replications each; Table~\ref{tab:stress-test}) confirms these patterns broadly: at $\varepsilon{=}0$, sign-flip rates are zero for all configurations; at $\varepsilon{=}0.10$, the maximum sign-flip rate is 7\% (IV, low-quality $C_{kk}{=}0.4$, $K{=}3$). At $K{=}10$, sign-flip rates remain zero for all topologies and $\varepsilon$ values, suggesting that higher $K$ provides additional robustness to differential misclassification.
914	
915	\input{exp_a_stress_test_table.tex}
916	
917	\subsection{Robustness to Nonlinear DGP}
918	\label{sec:logistic_dgp}
919	
920	We replace the linear structural equations with $Y \sim \text{Bernoulli}(\sigma(\mathbf{x}^\top\boldsymbol{\beta}))$ and estimate via logistic regression (control function for IV) for all seven topologies, using $K{=}3$, six real VAST confusion matrices, 500 MC replications, and $N{=}10{,}000$. Mean sign-flip rates across the six CMs:
921	
922	\begin{center}
923	\small
924	\begin{tabular}{lcccc}
925	\toprule
926	Topology & Linear SF$_\tau$ & Logistic SF$_\tau$ & Linear SF$_\text{any}$ & Logistic SF$_\text{any}$ \\
927	\midrule
928	Confounding & 0.000 & 0.000 & 0.573 & 0.559 \\
929	Mediation & 0.000 & 0.000 & 0.703 & 0.695 \\
930	Collider & 0.000 & 0.000 & 0.060 & 0.060 \\
931	Exposure & --- & --- & 0.577 & 0.574 \\
932	M-bias & 0.000 & 0.000 & 0.095 & 0.099 \\
933	Front-door & 0.000 & 0.000 & 0.590 & 0.579 \\
934	IV & 0.086 & 0.074 & 0.086 & 0.560 \\
935	\bottomrule
936	\end{tabular}
937	\end{center}
938	
939	Treatment-effect sign-flip rates (SF$_\tau$) are zero for all five guaranteed topologies under both linear and logistic DGPs, and differ by $< 0.02$ for IV. The SF$_\text{any}$ discrepancy for IV reflects estimator dimensionality: the control function includes a residual coefficient prone to sign noise; the core comparison is SF$_\tau$, where both estimators agree. Linear and logistic DGPs produce virtually identical sign-flip patterns across all seven topologies ($|\Delta\,\text{SF}_\tau| < 0.02$).
940	
941	\subsection{Bootstrap Uncertainty of ASV}
942	\label{sec:bootstrap_asv}
943	
944	We assess confusion-matrix estimation uncertainty by bootstrapping label pairs from HumAID DeepSeek zero-shot ($K{=}10$, $n{=}1{,}500$): resample with replacement $B{=}1{,}000$ times, re-estimate $C_0$, and recompute magnitude ASV $\delta^*$ at a 10\% bias threshold.
945	
946	\begin{center}
947	\small
948	\begin{tabular}{lccc}
949	\toprule
950	Topology & $\delta^*$ (point) & 95\% CI & Valid / 1000 \\
951	\midrule
952	Confounding & --- & --- & 0 \\
953	Exposure & 0.937 & [0.602, 1.363] & 907 \\
954	IV & 0.754 & [0.435, 1.290] & 902 \\
955	\bottomrule
956	\end{tabular}
957	\end{center}
958	
959	Confounding never reaches the 10\% threshold across all 1{,}000 bootstraps, confirming robustness. For IV, the 95\% CI spans a $3{\times}$ range (0.435 to 1.290); practitioners should bootstrap $C_0$ rather than rely on a point estimate when ASV is near the decision boundary.
960	
961	\begin{figure}[h]
962	\centering
963	\includegraphics[width=0.9\columnwidth]{exp_c_bootstrap_figure.pdf}
964	\caption{Bootstrap distribution of magnitude ASV $\delta^*$ ($B{=}1{,}000$) for HumAID DeepSeek zero-shot ($K{=}10$). Dashed line: point estimate; shaded: 95\% CI.}
965	\label{fig:bootstrap_asv}
966	\end{figure}
967	
968	\subsection{Cross-$K$ Robustness}
969	\label{sec:cross_k_robustness}
970	
971	All structural patterns persist at $K{=}5,7$ (100{,}000 matrices each): sign-flip guarantees hold for the same five topologies, and IV sign-flip rates remain within 51--53\%.
972	
973	\subsection{ASV Diagnostic Results}
974	\label{sec:asv_diagnostics}
975	
976	For HumAID ($K{=}10$, 56 scenarios), 55.4\% are flagged as magnitude-ASV-unsafe---IV, mediation, front-door, and exposure all trigger, while confounding, collider, and M-bias remain below 10\% bias (Figure~\ref{fig:asv_heatmap}). For CivilComments ($K{=}2$), 100\% of scenarios are ASV-unsafe despite $F_1$ ranging from $0.69$ (7B) to $0.82$ (frontier).
977	
978	Overlaying all 23 empirical matrices onto the theoretical Dirichlet violation-rate curves (Figure~\ref{fig:dirichlet_overlay}) confirms placement: VAST in the danger zone, HumAID mid-range, CivilComments approaching safe for exposure but still in IV amplification.
979	
980	\subsection{ASV Stability Across DGP Parameters}
981	\label{sec:asv_stability}
982	
983	We test whether ASV rankings are stable across different data-generating process (DGP) configurations by varying the treatment-effect vector $\boldsymbol{\beta}$ across three settings: alternating-large ($\boldsymbol{\beta}=[0,\,1.0,\,-0.5]$), same-sign ($\boldsymbol{\beta}=[0,\,0.5,\,0.3]$), and alternating-small ($\boldsymbol{\beta}=[0,\,0.2,\,-0.1]$), with $K{=}3$, $\tau{=}0.5$, and five $C_0$ diagonal values $\in\{0.5,0.6,0.7,0.8,0.9\}$.
984	
985	\input{exp_e_asv_stability_table.tex}
986	
987	Three patterns emerge (Table~\ref{tab:asv_stability}). First, IV magnitude ASV is identical across all three DGPs ($\delta^*{=}0.203$). This is a mathematical identity, not an empirical finding: the Wald estimator $\hat{\tau}_{\text{IV}} = \text{RF}/\text{FS}$ has $\boldsymbol{\beta}$ in both numerator and denominator, and the ratio depends only on $C$ and the first-stage structure, making ASV invariant to $\boldsymbol{\beta}$ by construction. Second, exposure ASV depends on the coefficient ratio structure: alternating-large ($\beta_2/\beta_1 = -0.5$) and alternating-small ($\beta_2/\beta_1 = -0.5$) share the same ratio and yield identical $\delta^*{=}0.090$, while same-sign ($\beta_2/\beta_1 = 0.6$) gives $\delta^*{=}0.223$---thus the experiment provides two distinct sign-structure conditions, not three. Third, confounding ASV depends on effect magnitudes: only alternating-large triggers the 10\% threshold ($\delta^*{=}0.348$); smaller effects never reach 10\% bias.
988	
989	Confounding is consistently the most robust topology (highest ASV or no violation), and M-bias remains immune (not shown). However, the relative fragility of exposure vs.\ IV inverts with coefficient sign structure: under alternating signs, exposure is most fragile ($0.090 < 0.203$); under same-sign effects, IV is most fragile ($0.203 < 0.223$). Practitioners should compute ASV with their specific DGP rather than relying on generic rankings.
990	
991	\subsection{Extended Conjecture Verification}
992	\label{sec:conjecture_verify}
993	
994	We test envelope monotonicity (Conjecture~\ref{conj:monotone}) by sampling 10{,}000 random $C_0$ matrices from Dirichlet$(1,\dots,1)$ per topology for $K \in \{3,5,7\}$ (210{,}000 total), sweeping $\delta$ in steps of 0.01, and counting matrices with at least one non-monotonic step exceeding tolerance $10^{-12}$. Bias at each $\delta$ is computed via analytic probability limits using Gauss--Hermite quadrature (100 points), eliminating sampling noise entirely.
995	
996	\begin{table}[h]
997	\centering
998	\small
999	\caption{Envelope monotonicity violations per 10{,}000 random $C_0$ matrices. ``Worst mag.''\ is the largest single-step deviation $|B(\delta_{i+1})|-|B(\delta_i)|$ in the non-monotonic direction.}
1000	\label{tab:conjecture_verify}
1001	\begin{tabular}{lccccc}
1002	\toprule
1003	\textbf{Topology} & $K{=}3$ & $K{=}5$ & $K{=}7$ & \textbf{Worst mag.} & \textbf{Direction} \\
1004	\midrule
1005	Confounding & 8467 & 8063 & 7892 & 0.011 & non-dec \\
1006	Mediation   & 8236 & 7905 & 7893 & 0.013 & non-dec \\
1007	Collider    & 8683 & 7669 & 7570 & 0.005 & non-inc \\
1008	Exposure    & 485  & 205  & 77   & 0.056 & non-dec \\
1009	M-bias      & 9791 & 7783 & 7399 & 0.002 & non-inc \\
1010	IV          & 7433 & 6015 & 5711 & $>10^6$ & non-dec \\
1011	Front-door  & 8429 & 8079 & 7899 & 0.013 & non-dec \\
1012	\bottomrule
1013	\end{tabular}
1014	\end{table}
1015	
1016	Violation counts are high (60--97\% of matrices), but magnitudes are negligible for non-IV topologies: all worst-case deviations fall below 0.06 ($<$6\% of the respective $\tau$). These results are computed from analytic probability limits with zero sampling noise, confirming the violations are structural properties of multi-class confusion matrices rather than numerical artifacts. IV deviations reflect Wald estimator singularities when the first-stage coefficient passes near zero---this is a property of the Wald estimator, not of the ASV parameterization. Adversarial search (500 restarts per configuration, $K \in \{3,5\}$) finds genuine counterexamples for all topologies except IV $K{=}3$, confirming that strict monotonicity does not hold universally. The bias envelope is $\varepsilon$-approximately monotonic with $\varepsilon < 0.03$ for collider and M-bias across all tested $\tau$; confounding, mediation, and front-door achieve $\varepsilon < 0.06$ at default DGP parameters (see DGP sensitivity below); exposure satisfies $\varepsilon_{p99} < 0.008$ but extreme-tail matrices ($<$0.02\% of draws) reach $\varepsilon \approx 0.15$. Empirically, $\varepsilon$ scales as $O(1/K^\alpha)$ with $\alpha \in [0.6, 1.5]$ (topology-dependent): for confounding, mediation, and front-door, $\alpha \approx 1.4$; for exposure, $\alpha \approx 1.0$; for collider and M-bias, $\alpha \approx 0.7$. A universal empirical upper bound is $\varepsilon \leq 0.137/\sqrt{K}$, verified across all tested configurations ($K \in \{3,5,7\}$). This scaling supports the practical validity of ASV as a sensitivity tool at any meaningful bias threshold.
1017	
1018	\paragraph{DGP parameter sensitivity.}
1019	We repeat the verification across $\tau \in \{0.1, 0.5, 1.0, 2.0, 5.0\}$, varying the direct $T{\to}Y$ coefficient for confounding ($\beta_T{=}\tau$), mediation, collider, and M-bias (DGP $\tau$), and rescaling the $A{\to}Y$ coefficient vector to $\boldsymbol{\beta}\cdot\tau$ for exposure and front-door. With 10{,}000 random $C_0$ per $(K,\tau)$ setting (Table~\ref{tab:conjecture_tau_sens}), the bound $\varepsilon{<}0.06$ holds uniformly for $\tau \geq 0.5$ for confounding, mediation, collider, and M-bias, but breaks down at $\tau{=}0.1$: mediation produces 1{,}950 / 30{,}000 violations across $K \in \{3,5,7\}$ (worst $\varepsilon{=}0.130$ at $K{=}3$) and confounding 200 / 30{,}000 (worst $\varepsilon{=}0.118$ at $K{=}3$). The mechanism is dimensional: additive terms not scaling with $\tau$ (e.g.\ the $\boldsymbol{\beta}$-contribution to $\mathbb{E}[Y D_k]$ in mediation and confounding) contribute a $\tau$-independent offset to the bias numerator, so the ratio $|B|/|\tau|$ inflates as $\tau \to 0$. A single mediation violation at $\tau{=}2.0$ ($\varepsilon{=}0.112$, 1/30{,}000 matrices) arises from a specific confusion matrix structure where off-diagonal entries induce partial cancellation along the mediation pathway; this isolated case does not affect the $p_{99}$ bound ($\varepsilon_{p99}{=}0.005$). Collider and M-bias remain robust at all $\tau$ ($\varepsilon{<}0.022$ and $\varepsilon{<}0.015$ respectively). Exposure shows scattered tail outliers but $\overline{\varepsilon} \approx 3\!\times\!10^{-4}$ at every $\tau$, consistent with linear scaling: when $\boldsymbol{\beta}$ rescales by $\tau$, both bias and $\tau_{\text{true}}$ scale by the same factor and $\varepsilon$ is theoretically invariant. Front-door inverts the pattern ($\varepsilon$ \emph{grows} with $\tau$, reaching $0.139$ at $\tau{=}5$, $K{=}3$, with 664 violations) because $\tau_{\text{true}} = \operatorname{plim}(\hat{\tau}_T \mid C{=}I)$ is pinned at $0.5$ by the $U$-confounding path while bias magnitudes scale with $\boldsymbol{\beta}$---this is an artefact of how $\tau_{\text{true}}$ is normalised, not a genuine failure of envelope monotonicity. In practice, ASV's $\delta^*$ thresholds (typically $\geq 0.1$ in our deployment) are well above the region where these $\varepsilon$-violations occur, so the small-$\tau$ degradation does not affect ASV's operational reliability; we flag it as a caveat for applications targeting $|\tau| \lesssim 0.1$ in standardised units.
1020	
1021	\begin{table}[h]
1022	\centering
1023	\small
1024	\caption{$\varepsilon \equiv \max_\delta(|B(\delta{+}\Delta)|{-}|B(\delta)|)/|\tau_{\text{true}}|$ in the non-monotonic direction (max over $K \in \{3,5,7\}$; 10{,}000 random $C_0$ per cell). Bold marks $\varepsilon > 0.06$. Counts in parentheses are violations / 30{,}000. Tables~\ref{tab:conjecture_verify} and~\ref{tab:conjecture_tau_sens} use independent random seeds; for topologies with low violation rates (exposure $<$0.02\%), the worst-case $\varepsilon$ is sample-sensitive.}
1025	\label{tab:conjecture_tau_sens}
1026	\begin{tabular}{lccccc}
1027	\toprule
1028	\textbf{Topology} & $\tau{=}0.1$ & $\tau{=}0.5$ & $\tau{=}1.0$ & $\tau{=}2.0$ & $\tau{=}5.0$ \\
1029	\midrule
1030	Confounding & \textbf{0.118} (200) & 0.027 (0) & 0.014 (0) & 0.007 (0) & 0.002 (0) \\
1031	Mediation   & \textbf{0.130} (1950) & 0.026 (0) & 0.013 (0) & \textbf{0.112} (1) & 0.003 (0) \\
1032	Collider    & 0.022 (0) & 0.006 (0) & 0.005 (0) & 0.004 (0) & 0.002 (0) \\
1033	Exposure    & \textbf{0.111} (5) & \textbf{0.122} (2) & \textbf{0.152} (2) & \textbf{0.089} (3) & \textbf{0.148} (3) \\
1034	M-bias      & 0.014 (0) & 0.003 (0) & 0.001 (0) & 0.001 (0) & 0.000 (0) \\
1035	Front-door  & 0.003 (0) & 0.013 (0) & 0.027 (0) & 0.051 (0) & \textbf{0.139} (664) \\
1036	\bottomrule
1037	\end{tabular}
1038	\end{table}
1039	
1040	\section{Notation}
1041	\label{app:notation_table}
1042	
1043	\begin{table}[h]
1044	\centering
1045	\small
1046	\caption{Key notation used throughout the paper.}
1047	\label{tab:notation}
1048	\begin{tabular}{cl}
1049	\toprule
1050	\textbf{Symbol} & \textbf{Description} \\
1051	\midrule
1052	$K$ & Number of annotation categories \\
1053	$C$ & Column-stochastic confusion matrix, $C_{jk} = P(A^*{=}j \mid A{=}k)$ \\
1054	$A$, $A^*$ & True and observed (misclassified) annotation \\
1055	$T$ & Treatment variable \\
1056	$Y$ & Outcome variable \\
1057	$\tau$ & Causal effect of interest \\
1058	$\delta$ & ASV perturbation parameter, $C(\delta) = (1{-}\delta)I + \delta C_0$ \\
1059	$\delta^*$ & Critical ASV value (magnitude/significance/sign-flip) \\
1060	$B(C)$ & Bias function, $= \operatorname{plim}(\hat{\tau}) - \tau$ \\
1061	$\beta_k$ & Treatment effect coefficient for category $k$ \\
1062	$D_k$ & Dummy variable for category $k$ \\
1063	\bottomrule
1064	\end{tabular}
1065	\end{table}
1066	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9a21eb4c-63de-4ce7-97c5-c734911953c7",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "085f0bcd-a8fd-4953-be44-46ea3c6cd9b9",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\small\n\\begin{algorithmic}[1]\n\\REQUIRE DAG topology $\\mathcal{T}$, gold-label availability $G \\in \\{\\textsc{yes}, \\textsc{no}\\}$\n\\ENSURE Recommended method $M$, risk level $R$\n\\STATE\n\\STATE \\textbf{Step 1: Assess risk level}\n\\IF{$\\mathcal{T} \\in \\{\\text{M-bias}\\}$}\n    \\STATE $R \\gets \\textsc{Low}$ \\COMMENT{$|\\text{bias}| < 0.04$ for all $C$}\n\\ELSIF{$\\mathcal{T} \\in \\{\\text{Conf., Med., Coll., Front-door}\\}$}\n    \\STATE $R \\gets \\textsc{Medium}$ \\COMMENT{bounded bias, no sign reversal}\n\\ELSE\n    \\STATE $R \\gets \\textsc{High}$ \\COMMENT{Exposure, IV: sign reversal 83.4\\% / 52.6\\%}\n\\ENDIF\n\\STATE\n\\STATE \\textbf{Step 2: Select correction method}\n\\IF{$G = \\textsc{yes}$}\n    \\IF{$\\mathcal{T} = \\text{M-bias}$}\n        \\STATE $M \\gets \\textsc{None}$ \\COMMENT{PPI++ RMSE red.\\ $-$88.0\\%; no correction preferred}\n    \\ELSE\n        \\STATE $M \\gets \\text{PPI++}$ \\COMMENT{47.0\\% RMSE red., 96.8\\% coverage}\n    \\ENDIF\n\\ELSE\n    \\STATE \\COMMENT{no gold labels}\n    \\IF{$\\mathcal{T} \\in \\{\\text{Confounding, Mediation}\\}$}\n        \\STATE $M \\gets \\text{DSL}$ \\COMMENT{48.0\\% / 52.9\\% RMSE reduction}\n    \\ELSIF{$\\mathcal{T} = \\text{IV}$}\n        \\STATE $M \\gets \\text{MC-SIMEX}$ \\COMMENT{59.4\\% RMSE reduction}\n    \\ELSIF{$\\mathcal{T} \\in \\{\\text{Collider, M-bias}\\}$}\n        \\STATE $M \\gets \\text{MC-SIMEX}$ \\COMMENT{31.8\\% / 0.1\\% RMSE reduction}\n    \\ELSE\n        \\STATE $M \\gets \\emptyset$; flag: acquire gold labels \\COMMENT{no reliable gold-free method}\n    \\ENDIF\n\\ENDIF\n\\STATE\n\\STATE \\textbf{Step 3: FWL invariance warning}\n\\IF{$\\mathcal{T} \\in \\{\\text{Conf., Med., Coll., M-bias}\\}$}\n    \\STATE Skip Naive plug-in and MLA \\COMMENT{0\\% bias red.\\ on $T$ coeff.}\n\\ENDIF\n\\RETURN $(M, R)$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\subsection{Proof of FWL Invariance}\n\\label{app:fwl_proof}\n\nFor the four topologies where $A$ enters as a covariate (confounding, mediation, collider, M-bias), the regression is $Y = \\tau T + \\boldsymbol{\\gamma}^\\top \\mathbf{D}^* + \\varepsilon$, where $\\mathbf{D}^*$ is the $N \\times (K{-}1)$ dummy matrix for $A^*$. Any matrix-based correction replaces $\\mathbf{D}^*$ with $\\tilde{\\mathbf{D}} = \\mathbf{D}^* M$ for some invertible $(K{-}1) \\times (K{-}1)$ matrix $M$ (e.g., $M = C^{-1}$ for plug-in, or $M = (C^\\top C)^{-1} C^\\top$ for MLE). By the Frisch--Waugh--Lovell theorem~\\cite{lovell1963}, $\\hat{\\tau}$ depends only on the residual of $T$ projected off $\\operatorname{col}(\\mathbf{D}^*)$. Since $\\operatorname{col}(\\mathbf{D}^* M) = \\operatorname{col}(\\mathbf{D}^*)$ for invertible $M$, the projection is unchanged and $\\hat{\\tau}(\\tilde{\\mathbf{D}}) = \\hat{\\tau}(\\mathbf{D}^*)$ exactly. SIMEX adds noise $\\mathbf{D}^*_{\\text{sim}} = \\mathbf{D}^* + \\lambda \\mathbf{E}$; when $\\mathbf{E}$ is generated from the same column space, the extrapolation to $\\lambda = -1$ converges to a column-space-equivalent transformation, yielding 0\\% bias reduction empirically.\n\n\\subsection{Applied Illustration: ClinicalBERT Case Study}\n\\label{app:case_study}\n\nTo demonstrate the framework's end-to-end utility, we apply it retrospectively to \\citet{lee_wood_doughty2024}, who use ClinicalBERT to classify patient smoking status ($K{=}4$: never, past, current, unknown) from clinical notes and control for this predicted confounder when estimating the causal effect of echocardiography on mortality in 4{,}735 MIMIC-III sepsis patients.\nOur taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.\nThree conclusions follow directly.\nFirst, the zero sign-flip guarantee for confounding (Table~\\ref{tab:taxonomy}) ensures that the estimated protective effect (OR~$= 0.89$) cannot reverse direction due to annotation error---a reassurance unavailable without topology-specific analysis.\nSecond, the FWL invariance result implies that any correction reducing to $C^{-1}$ applied to the dummy-coded confounder achieves exactly 0\\% bias reduction for the treatment coefficient; naive plug-in is provably futile here.\nThird, our correction guidance ranks PPI++ (83.2\\% RMSE reduction for confounding) above MC-SIMEX (35.1\\%) when gold labels are available---a concrete recommendation the original study lacked.\nThis example illustrates the intended workflow: DAG identification $\\to$ topology-specific guarantees $\\to$ correction method selection.\n\n\\subsection{IV Wald Estimator: Diagonal-Dominance Subspaces}\n\\label{sec:iv_dirichlet_subspace}\n\nSection~\\ref{sec:taxonomy_results} reports a 52.6\\% Wald sign-flip rate\nover the full Dirichlet$(1,1,1)$ prior. Because realistic LLM confusion\nmatrices are diagonal-dominant, we replicate the exposure-DAG stratification\nfor the IV topology, restricting the sample\nspace to $\\{C : \\min_k C_{kk} \\geq d\\}$ for $d \\in \\{0, 0.5, 0.7, 0.9\\}$\n(100{,}000 random matrices per threshold).\n\n\\begin{table}[h]\n\\centering\n\\caption{IV Wald estimator bias by minimum-diagonal subspace ($K{=}3$, $\\tau_{\\text{true}}{=}1.41$).\nRates over 100{,}000 Dirichlet-truncated random $C$ per threshold.}\n\\label{tab:iv_dirichlet_subspace}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Subspace} & \\textbf{Violation} & \\textbf{Sign Flip} & \\textbf{Amplif.} & \\textbf{Worst} \\\\\n\\midrule\nFull           & 100.0\\% & 51.7\\% & 48.3\\% & $10^{5}\\!\\times$ \\\\\n$d \\geq 0.5$   & 100.0\\% & 0.0\\%  & 100.0\\% & $28.6\\times$ \\\\\n$d \\geq 0.7$   & 100.0\\% & 0.0\\%  & 100.0\\% & $2.4\\times$ \\\\\n$d \\geq 0.9$   & 100.0\\% & 0.0\\%  & 100.0\\% & $1.2\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe contrast with exposure is instructive: at $d{\\geq}0.7$, exposure violation drops to 13.7\\% (sign reversal 2.1\\%, amplification 11.7\\%), while IV maintains 100\\% violation with pure amplification. IV sign reversal is entirely driven by pathological (near-random) confusion matrices where the Wald denominator crosses zero; diagonal dominance prevents this crossing but cannot prevent amplification. Even at $d{\\geq}0.9$, the Wald estimator inflates $|\\tau|$ by up to $1.24\\times$ with probability~1.\n\n\\subsection{Non-Differential Assumption Stress Test}\n\\label{sec:nondiff_stress}\n\nOur main analysis assumes non-differential misclassification: the confusion matrix $C$ does not depend on the outcome $Y$. To assess sensitivity to violations of this assumption, we conduct a stress test on the exposure topology ($K{=}3$, $\\min_k C_{kk} \\geq 0.7$, 10{,}000 random matrices per $\\varepsilon$). For each base matrix $C_0$, observations with $Y > \\text{median}(Y)$ are misclassified using a perturbed matrix $\\tilde{C} = \\text{renormalize}(C_0 + \\varepsilon \\cdot \\Delta)$ where $\\Delta_{jk} \\sim \\text{Uniform}(-1,1)$ for $j \\neq k$, while observations with $Y \\leq \\text{median}(Y)$ retain $C_0$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Effect of differential misclassification on bias violation rates (exposure DAG, $K{=}3$, $\\min_k C_{kk} \\geq 0.7$, $N{=}50{,}000$ MC samples per trial).}\n\\label{tab:nondiff_stress}\n\\begin{tabular}{cccc}\n\\toprule\n$\\varepsilon$ & Sign-Flip (\\%) & Amplification (\\%) & Any Violation (\\%) \\\\\n\\midrule\n0.00 & 2.0 & 11.5 & 13.3 \\\\\n0.01 & 2.4 & 12.4 & 14.7 \\\\\n0.05 & 2.8 & 13.0 & 15.7 \\\\\n0.10 & 4.5 & 16.7 & 20.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe $\\varepsilon{=}0$ baseline (13.3\\% violation) closely matches the analytical result (13.7\\%) from Section~\\ref{sec:taxonomy_results}. Even at $\\varepsilon{=}0.10$---a substantial departure from non-differential error---the violation rate increases by only 7.6 percentage points. Small departures ($\\varepsilon \\leq 0.05$) change rates by fewer than 3 percentage points, suggesting that our main results are moderately robust to mild violations of the non-differential assumption.\n\n\\paragraph{Extended stress test.}\nAn extended stress test across 96 configurations (4 topologies $\\times$ 2 $K$ $\\times$ 3 CM qualities $\\times$ 4 $\\varepsilon$, 100 MC replications each; Table~\\ref{tab:stress-test}) confirms these patterns broadly: at $\\varepsilon{=}0$, sign-flip rates are zero for all configurations; at $\\varepsilon{=}0.10$, the maximum sign-flip rate is 7\\% (IV, low-quality $C_{kk}{=}0.4$, $K{=}3$). At $K{=}10$, sign-flip rates remain zero for all topologies and $\\varepsilon$ values, suggesting that higher $K$ provides additional robustness to differential misclassification.\n\n\\input{exp_a_stress_test_table.tex}\n\n\\subsection{Robustness to Nonlinear DGP}\n\\label{sec:logistic_dgp}\n\nWe replace the linear structural equations with $Y \\sim \\text{Bernoulli}(\\sigma(\\mathbf{x}^\\top\\boldsymbol{\\beta}))$ and estimate via logistic regression (control function for IV) for all seven topologies, using $K{=}3$, six real VAST confusion matrices, 500 MC replications, and $N{=}10{,}000$. Mean sign-flip rates across the six CMs:\n\n\\begin{center}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTopology & Linear SF$_\\tau$ & Logistic SF$_\\tau$ & Linear SF$_\\text{any}$ & Logistic SF$_\\text{any}$ \\\\\n\\midrule\nConfounding & 0.000 & 0.000 & 0.573 & 0.559 \\\\\nMediation & 0.000 & 0.000 & 0.703 & 0.695 \\\\\nCollider & 0.000 & 0.000 & 0.060 & 0.060 \\\\\nExposure & --- & --- & 0.577 & 0.574 \\\\\nM-bias & 0.000 & 0.000 & 0.095 & 0.099 \\\\\nFront-door & 0.000 & 0.000 & 0.590 & 0.579 \\\\\nIV & 0.086 & 0.074 & 0.086 & 0.560 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{center}\n\nTreatment-effect sign-flip rates (SF$_\\tau$) are zero for all five guaranteed topologies under both linear and logistic DGPs, and differ by $< 0.02$ for IV. The SF$_\\text{any}$ discrepancy for IV reflects estimator dimensionality: the control function includes a residual coefficient prone to sign noise; the core comparison is SF$_\\tau$, where both estimators agree. Linear and logistic DGPs produce virtually identical sign-flip patterns across all seven topologies ($|\\Delta\\,\\text{SF}_\\tau| < 0.02$).\n\n\\subsection{Bootstrap Uncertainty of ASV}\n\\label{sec:bootstrap_asv}\n\nWe assess confusion-matrix estimation uncertainty by bootstrapping label pairs from HumAID DeepSeek zero-shot ($K{=}10$, $n{=}1{,}500$): resample with replacement $B{=}1{,}000$ times, re-estimate $C_0$, and recompute magnitude ASV $\\delta^*$ at a 10\\% bias threshold.\n\n\\begin{center}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nTopology & $\\delta^*$ (point) & 95\\% CI & Valid / 1000 \\\\\n\\midrule\nConfounding & --- & --- & 0 \\\\\nExposure & 0.937 & [0.602, 1.363] & 907 \\\\\nIV & 0.754 & [0.435, 1.290] & 902 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{center}\n\nConfounding never reaches the 10\\% threshold across all 1{,}000 bootstraps, confirming robustness. For IV, the 95\\% CI spans a $3{\\times}$ range (0.435 to 1.290); practitioners should bootstrap $C_0$ rather than rely on a point estimate when ASV is near the decision boundary.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.9\\columnwidth]{exp_c_bootstrap_figure.pdf}\n\\caption{Bootstrap distribution of magnitude ASV $\\delta^*$ ($B{=}1{,}000$) for HumAID DeepSeek zero-shot ($K{=}10$). Dashed line: point estimate; shaded: 95\\% CI.}\n\\label{fig:bootstrap_asv}\n\\end{figure}\n\n\\subsection{Cross-$K$ Robustness}\n\\label{sec:cross_k_robustness}\n\nAll structural patterns persist at $K{=}5,7$ (100{,}000 matrices each): sign-flip guarantees hold for the same five topologies, and IV sign-flip rates remain within 51--53\\%.\n\n\\subsection{ASV Diagnostic Results}\n\\label{sec:asv_diagnostics}\n\nFor HumAID ($K{=}10$, 56 scenarios), 55.4\\% are flagged as magnitude-ASV-unsafe---IV, mediation, front-door, and exposure all trigger, while confounding, collider, and M-bias remain below 10\\% bias (Figure~\\ref{fig:asv_heatmap}). For CivilComments ($K{=}2$), 100\\% of scenarios are ASV-unsafe despite $F_1$ ranging from $0.69$ (7B) to $0.82$ (frontier).\n\nOverlaying all 23 empirical matrices onto the theoretical Dirichlet violation-rate curves (Figure~\\ref{fig:dirichlet_overlay}) confirms placement: VAST in the danger zone, HumAID mid-range, CivilComments approaching safe for exposure but still in IV amplification.\n\n\\subsection{ASV Stability Across DGP Parameters}\n\\label{sec:asv_stability}\n\nWe test whether ASV rankings are stable across different data-generating process (DGP) configurations by varying the treatment-effect vector $\\boldsymbol{\\beta}$ across three settings: alternating-large ($\\boldsymbol{\\beta}=[0,\\,1.0,\\,-0.5]$), same-sign ($\\boldsymbol{\\beta}=[0,\\,0.5,\\,0.3]$), and alternating-small ($\\boldsymbol{\\beta}=[0,\\,0.2,\\,-0.1]$), with $K{=}3$, $\\tau{=}0.5$, and five $C_0$ diagonal values $\\in\\{0.5,0.6,0.7,0.8,0.9\\}$.\n\n\\input{exp_e_asv_stability_table.tex}\n\nThree patterns emerge (Table~\\ref{tab:asv_stability}). First, IV magnitude ASV is identical across all three DGPs ($\\delta^*{=}0.203$). This is a mathematical identity, not an empirical finding: the Wald estimator $\\hat{\\tau}_{\\text{IV}} = \\text{RF}/\\text{FS}$ has $\\boldsymbol{\\beta}$ in both numerator and denominator, and the ratio depends only on $C$ and the first-stage structure, making ASV invariant to $\\boldsymbol{\\beta}$ by construction. Second, exposure ASV depends on the coefficient ratio structure: alternating-large ($\\beta_2/\\beta_1 = -0.5$) and alternating-small ($\\beta_2/\\beta_1 = -0.5$) share the same ratio and yield identical $\\delta^*{=}0.090$, while same-sign ($\\beta_2/\\beta_1 = 0.6$) gives $\\delta^*{=}0.223$---thus the experiment provides two distinct sign-structure conditions, not three. Third, confounding ASV depends on effect magnitudes: only alternating-large triggers the 10\\% threshold ($\\delta^*{=}0.348$); smaller effects never reach 10\\% bias.\n\nConfounding is consistently the most robust topology (highest ASV or no violation), and M-bias remains immune (not shown). However, the relative fragility of exposure vs.\\ IV inverts with coefficient sign structure: under alternating signs, exposure is most fragile ($0.090 < 0.203$); under same-sign effects, IV is most fragile ($0.203 < 0.223$). Practitioners should compute ASV with their specific DGP rather than relying on generic rankings.\n\n\\subsection{Extended Conjecture Verification}\n\\label{sec:conjecture_verify}\n\nWe test envelope monotonicity (Conjecture~\\ref{conj:monotone}) by sampling 10{,}000 random $C_0$ matrices from Dirichlet$(1,\\dots,1)$ per topology for $K \\in \\{3,5,7\\}$ (210{,}000 total), sweeping $\\delta$ in steps of 0.01, and counting matrices with at least one non-monotonic step exceeding tolerance $10^{-12}$. Bias at each $\\delta$ is computed via analytic probability limits using Gauss--Hermite quadrature (100 points), eliminating sampling noise entirely.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Envelope monotonicity violations per 10{,}000 random $C_0$ matrices. ``Worst mag.''\\ is the largest single-step deviation $|B(\\delta_{i+1})|-|B(\\delta_i)|$ in the non-monotonic direction.}\n\\label{tab:conjecture_verify}\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Topology} & $K{=}3$ & $K{=}5$ & $K{=}7$ & \\textbf{Worst mag.} & \\textbf{Direction} \\\\\n\\midrule\nConfounding & 8467 & 8063 & 7892 & 0.011 & non-dec \\\\\nMediation   & 8236 & 7905 & 7893 & 0.013 & non-dec \\\\\nCollider    & 8683 & 7669 & 7570 & 0.005 & non-inc \\\\\nExposure    & 485  & 205  & 77   & 0.056 & non-dec \\\\\nM-bias      & 9791 & 7783 & 7399 & 0.002 & non-inc \\\\\nIV          & 7433 & 6015 & 5711 & $>10^6$ & non-dec \\\\\nFront-door  & 8429 & 8079 & 7899 & 0.013 & non-dec \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nViolation counts are high (60--97\\% of matrices), but magnitudes are negligible for non-IV topologies: all worst-case deviations fall below 0.06 ($<$6\\% of the respective $\\tau$). These results are computed from analytic probability limits with zero sampling noise, confirming the violations are structural properties of multi-class confusion matrices rather than numerical artifacts. IV deviations reflect Wald estimator singularities when the first-stage coefficient passes near zero---this is a property of the Wald estimator, not of the ASV parameterization. Adversarial search (500 restarts per configuration, $K \\in \\{3,5\\}$) finds genuine counterexamples for all topologies except IV $K{=}3$, confirming that strict monotonicity does not hold universally. The bias envelope is $\\varepsilon$-approximately monotonic with $\\varepsilon < 0.03$ for collider and M-bias across all tested $\\tau$; confounding, mediation, and front-door achieve $\\varepsilon < 0.06$ at default DGP parameters (see DGP sensitivity below); exposure satisfies $\\varepsilon_{p99} < 0.008$ but extreme-tail matrices ($<$0.02\\% of draws) reach $\\varepsilon \\approx 0.15$. Empirically, $\\varepsilon$ scales as $O(1/K^\\alpha)$ with $\\alpha \\in [0.6, 1.5]$ (topology-dependent): for confounding, mediation, and front-door, $\\alpha \\approx 1.4$; for exposure, $\\alpha \\approx 1.0$; for collider and M-bias, $\\alpha \\approx 0.7$. A universal empirical upper bound is $\\varepsilon \\leq 0.137/\\sqrt{K}$, verified across all tested configurations ($K \\in \\{3,5,7\\}$). This scaling supports the practical validity of ASV as a sensitivity tool at any meaningful bias threshold.\n\n\\paragraph{DGP parameter sensitivity.}\nWe repeat the verification across $\\tau \\in \\{0.1, 0.5, 1.0, 2.0, 5.0\\}$, varying the direct $T{\\to}Y$ coefficient for confounding ($\\beta_T{=}\\tau$), mediation, collider, and M-bias (DGP $\\tau$), and rescaling the $A{\\to}Y$ coefficient vector to $\\boldsymbol{\\beta}\\cdot\\tau$ for exposure and front-door. With 10{,}000 random $C_0$ per $(K,\\tau)$ setting (Table~\\ref{tab:conjecture_tau_sens}), the bound $\\varepsilon{<}0.06$ holds uniformly for $\\tau \\geq 0.5$ for confounding, mediation, collider, and M-bias, but breaks down at $\\tau{=}0.1$: mediation produces 1{,}950 / 30{,}000 violations across $K \\in \\{3,5,7\\}$ (worst $\\varepsilon{=}0.130$ at $K{=}3$) and confounding 200 / 30{,}000 (worst $\\varepsilon{=}0.118$ at $K{=}3$). The mechanism is dimensional: additive terms not scaling with $\\tau$ (e.g.\\ the $\\boldsymbol{\\beta}$-contribution to $\\mathbb{E}[Y D_k]$ in mediation and confounding) contribute a $\\tau$-independent offset to the bias numerator, so the ratio $|B|/|\\tau|$ inflates as $\\tau \\to 0$. A single mediation violation at $\\tau{=}2.0$ ($\\varepsilon{=}0.112$, 1/30{,}000 matrices) arises from a specific confusion matrix structure where off-diagonal entries induce partial cancellation along the mediation pathway; this isolated case does not affect the $p_{99}$ bound ($\\varepsilon_{p99}{=}0.005$). Collider and M-bias remain robust at all $\\tau$ ($\\varepsilon{<}0.022$ and $\\varepsilon{<}0.015$ respectively). Exposure shows scattered tail outliers but $\\overline{\\varepsilon} \\approx 3\\!\\times\\!10^{-4}$ at every $\\tau$, consistent with linear scaling: when $\\boldsymbol{\\beta}$ rescales by $\\tau$, both bias and $\\tau_{\\text{true}}$ scale by the same factor and $\\varepsilon$ is theoretically invariant. Front-door inverts the pattern ($\\varepsilon$ \\emph{grows} with $\\tau$, reaching $0.139$ at $\\tau{=}5$, $K{=}3$, with 664 violations) because $\\tau_{\\text{true}} = \\operatorname{plim}(\\hat{\\tau}_T \\mid C{=}I)$ is pinned at $0.5$ by the $U$-confounding path while bias magnitudes scale with $\\boldsymbol{\\beta}$---this is an artefact of how $\\tau_{\\text{true}}$ is normalised, not a genuine failure of envelope monotonicity. In practice, ASV's $\\delta^*$ thresholds (typically $\\geq 0.1$ in our deployment) are well above the region where these $\\varepsilon$-violations occur, so the small-$\\tau$ degradation does not affect ASV's operational reliability; we flag it as a caveat for applications targeting $|\\tau| \\lesssim 0.1$ in standardised units.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{$\\varepsilon \\equiv \\max_\\delta(|B(\\delta{+}\\Delta)|{-}|B(\\delta)|)/|\\tau_{\\text{true}}|$ in the non-monotonic direction (max over $K \\in \\{3,5,7\\}$; 10{,}000 random $C_0$ per cell). Bold marks $\\varepsilon > 0.06$. Counts in parentheses are violations / 30{,}000. Tables~\\ref{tab:conjecture_verify} and~\\ref{tab:conjecture_tau_sens} use independent random seeds; for topologies with low violation rates (exposure $<$0.02\\%), the worst-case $\\varepsilon$ is sample-sensitive.}\n\\label{tab:conjecture_tau_sens}\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Topology} & $\\tau{=}0.1$ & $\\tau{=}0.5$ & $\\tau{=}1.0$ & $\\tau{=}2.0$ & $\\tau{=}5.0$ \\\\\n\\midrule\nConfounding & \\textbf{0.118} (200) & 0.027 (0) & 0.014 (0) & 0.007 (0) & 0.002 (0) \\\\\nMediation   & \\textbf{0.130} (1950) & 0.026 (0) & 0.013 (0) & \\textbf{0.112} (1) & 0.003 (0) \\\\\nCollider    & 0.022 (0) & 0.006 (0) & 0.005 (0) & 0.004 (0) & 0.002 (0) \\\\\nExposure    & \\textbf{0.111} (5) & \\textbf{0.122} (2) & \\textbf{0.152} (2) & \\textbf{0.089} (3) & \\textbf{0.148} (3) \\\\\nM-bias      & 0.014 (0) & 0.003 (0) & 0.001 (0) & 0.001 (0) & 0.000 (0) \\\\\nFront-door  & 0.003 (0) & 0.013 (0) & 0.027 (0) & 0.051 (0) & \\textbf{0.139} (664) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Notation}\n\\label{app:notation_table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Key notation used throughout the paper.}\n\\label{tab:notation}\n\\begin{tabular}{cl}\n\\toprule\n\\textbf{Symbol} & \\textbf{Description} \\\\\n\\midrule\n$K$ & Number of annotation categories \\\\\n$C$ & Column-stochastic confusion matrix, $C_{jk} = P(A^*{=}j \\mid A{=}k)$ \\\\\n$A$, $A^*$ & True and observed (misclassified) annotation \\\\\n$T$ & Treatment variable \\\\\n$Y$ & Outcome variable \\\\\n$\\tau$ & Causal effect of interest \\\\\n$\\delta$ & ASV perturbation parameter, $C(\\delta) = (1{-}\\delta)I + \\delta C_0$ \\\\\n$\\delta^*$ & Critical ASV value (magnitude/significance/sign-flip) \\\\\n$B(C)$ & Bias function, $= \\operatorname{plim}(\\hat{\\tau}) - \\tau$ \\\\\n$\\beta_k$ & Treatment effect coefficient for category $k$ \\\\\n$D_k$ & Dummy variable for category $k$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n",
      "numLines": 267,
      "startLine": 800,
      "totalLines": 1066
    }
  },
  "sourceToolAssistantUUID": "9a21eb4c-63de-4ce7-97c5-c734911953c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 47_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "085f0bcd-a8fd-4953-be44-46ea3c6cd9b9",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Assistant

_source line 48 · 2026-05-22T16:55:27.539Z_

<details><summary>Logged reasoning block</summary>

```text
I've now read the entire paper thoroughly. Let me also check the references file briefly to understand the citation landscape.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "085f0bcd-a8fd-4953-be44-46ea3c6cd9b9",
  "isSidechain": false,
  "requestId": "req_011CbHxYHaDaqm8D22AhwYbs",
  "type": "assistant",
  "uuid": "675a1bad-b5dd-4bcd-8c6c-f7366311a691",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0116MveyYTvMLtaxBus6GoFW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8914,
      "cache_read_input_tokens": 68610,
      "output_tokens": 244,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8914,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 244,
          "cache_read_input_tokens": 68610,
          "cache_creation_input_tokens": 8914,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8914
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

_source line 49 · 2026-05-22T16:55:28.023Z_

Now let me check the references and page count.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "675a1bad-b5dd-4bcd-8c6c-f7366311a691",
  "isSidechain": false,
  "requestId": "req_011CbHxYHaDaqm8D22AhwYbs",
  "type": "assistant",
  "uuid": "0c106865-92e3-46dc-a217-5dee7fa2af63",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0116MveyYTvMLtaxBus6GoFW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8914,
      "cache_read_input_tokens": 68610,
      "output_tokens": 244,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8914,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 244,
          "cache_read_input_tokens": 68610,
          "cache_creation_input_tokens": 8914,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8914
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

_source line 50 · 2026-05-22T16:55:29.898Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NpLhmS8L7T7H6631gLH2D7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/references.bib",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0c106865-92e3-46dc-a217-5dee7fa2af63",
  "isSidechain": false,
  "requestId": "req_011CbHxYHaDaqm8D22AhwYbs",
  "type": "assistant",
  "uuid": "198b8b18-46a9-404a-999b-f10be92b3751",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0116MveyYTvMLtaxBus6GoFW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8914,
      "cache_read_input_tokens": 68610,
      "output_tokens": 244,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8914,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 244,
          "cache_read_input_tokens": 68610,
          "cache_creation_input_tokens": 8914,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8914
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

_source line 51 · 2026-05-22T16:55:30.581Z_

<details><summary>↩ Tool result · `toolu_01TKS9uwsB5agMYB9LBEJ6JD`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__review_reviewer_post_to_director"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__pdf_to_images"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ffe362d4-526d-4d22-b025-18a8cb888b47",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "cb75bb77-c81e-4917-ab9d-5b6c59359eec",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__pdf_to_images"
    ],
    "query": "select:mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__pdf_to_images",
    "total_deferred_tools": 22
  },
  "sourceToolAssistantUUID": "ffe362d4-526d-4d22-b025-18a8cb888b47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 52 · 2026-05-22T16:55:29.926Z_

<details><summary>↩ Tool result · `toolu_01NpLhmS8L7T7H6631gLH2D7`</summary>

```text
1	% Auto-generated from literature_map.yaml — all verified=true entries
2	% Last sync: 2026-05-20
3	
4	@article{cinelli2020making,
5	  author    = {Cinelli, Carlos and Hazlett, Chad},
6	  title     = {Making Sense of Sensitivity: Extending Omitted Variable Bias},
7	  journal   = {Journal of the Royal Statistical Society: Series B (Statistical Methodology)},
8	  year      = {2020},
9	  volume    = {82},
10	  number    = {1},
11	  pages     = {39--67},
12	  doi       = {10.1111/rssb.12348},
13	}
14	
15	@article{gilardi2023chatgpt,
16	  author    = {Gilardi, Fabrizio and Alizadeh, Meysam and Kubli, Ma\"{e}l},
17	  title     = {{ChatGPT} Outperforms Crowd Workers for Text-Annotation Tasks},
18	  journal   = {Proceedings of the National Academy of Sciences},
19	  year      = {2023},
20	  volume    = {120},
21	  number    = {30},
22	  pages     = {e2305016120},
23	  doi       = {10.1073/pnas.2305016120},
24	}
25	
26	@article{ziems2024can,
27	  author    = {Ziems, Caleb and Held, William and Shaikh, Omar and Chen, Jiaao and Zhang, Zhehao and Yang, Diyi},
28	  title     = {Can Large Language Models Transform Computational Social Science?},
29	  journal   = {Computational Linguistics},
30	  year      = {2024},
31	  volume    = {50},
32	  number    = {1},
33	  pages     = {237--291},
34	  doi       = {10.1162/coli\_a\_00502},
35	}
36	
37	@incollection{bound2001measurement,
38	  author    = {Bound, John and Brown, Charles and Mathiowetz, Nancy},
39	  title     = {Measurement Error in Survey Data},
40	  booktitle = {Handbook of Econometrics},
41	  editor    = {Heckman, James J. and Leamer, Edward E.},
42	  year      = {2001},
43	  volume    = {5},
44	  chapter   = {59},
45	  pages     = {3705--3843},
46	  publisher = {Elsevier},
47	}
48	
49	@article{richardson1993bayesian,
50	  author    = {Richardson, Sylvia and Gilks, Walter R.},
51	  title     = {A {Bayesian} Approach to Measurement Error Problems in Epidemiology Using Conditional Independence Models},
52	  journal   = {American Journal of Epidemiology},
53	  year      = {1993},
54	  volume    = {138},
55	  number    = {6},
56	  pages     = {430--442},
57	  doi       = {10.1093/oxfordjournals.aje.a116875},
58	}
59	
60	@article{lovell1963,
61	  author  = {Lovell, Michael C.},
62	  title   = {Seasonal Adjustment of Economic Time Series and Multiple Regression Analysis},
63	  journal = {Journal of the American Statistical Association},
64	  year    = {1963},
65	  volume  = {58},
66	  number  = {304},
67	  pages   = {993--1010},
68	}
69	
70	@inproceedings{wood_doughty2018,
71	  title     = {Challenges of Using Text Classifiers for Causal Inference},
72	  author    = {Wood-Doughty, Zach and Shpitser, Ilya and Dredze, Mark},
73	  booktitle = {Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing},
74	  year      = {2018},
75	  doi       = {10.18653/v1/D18-1488},
76	}
77	
78	@article{teblunthuis2024,
79	  title   = {Misclassification in Automated Content Analysis Causes Bias in Regression. {C}an We Fix It? {Y}es We Can!},
80	  author  = {TeBlunthuis, Nathan and Hase, Valerie and Chan, Chung-hong},
81	  journal = {Communication Methods and Measures},
82	  volume  = {18},
83	  number  = {3},
84	  pages   = {278--299},
85	  year    = {2024},
86	  doi     = {10.1080/19312458.2023.2293713},
87	}
88	
89	@article{hernan_cole2009,
90	  title   = {Invited Commentary: Causal Diagrams and Measurement Bias},
91	  author  = {Hern{\'a}n, Miguel A. and Cole, Stephen R.},
92	  journal = {American Journal of Epidemiology},
93	  volume  = {170},
94	  number  = {8},
95	  pages   = {959--962},
96	  year    = {2009},
97	  doi     = {10.1093/aje/kwp293},
98	}
99	
100	
101	@article{vanderweele_ding2017,
102	  title   = {Sensitivity Analysis in Observational Research: Introducing the {E}-Value},
103	  author  = {VanderWeele, Tyler J. and Ding, Peng},
104	  journal = {Annals of Internal Medicine},
105	  volume  = {167},
106	  pages   = {268--274},
107	  year    = {2017},
108	  doi     = {10.7326/M16-2607},
109	}
110	
111	@article{imai_keele_yamamoto2010,
112	  title   = {Identification, Inference and Sensitivity Analysis for Causal Mediation Effects},
113	  author  = {Imai, Kosuke and Keele, Luke and Yamamoto, Teppei},
114	  journal = {Statistical Science},
115	  volume  = {25},
116	  number  = {1},
117	  pages   = {51--71},
118	  year    = {2010},
119	  doi     = {10.1214/10-STS321},
120	}
121	
122	@article{valeri_vanderweele2013,
123	  title   = {Mediation Analysis Allowing for Exposure-Mediator Interactions and Causal Interpretation: Theoretical Assumptions and Implementation with {SAS} and {SPSS} Macros},
124	  author  = {Valeri, Linda and VanderWeele, Tyler J.},
125	  journal = {Psychological Methods},
126	  volume  = {18},
127	  number  = {2},
128	  pages   = {137--150},
129	  year    = {2013},
130	  doi     = {10.1037/a0031034},
131	}
132	
133	@article{brenner1993,
134	  title   = {Bias Due to Non-differential Misclassification of Polytomous Confounders},
135	  author  = {Brenner, Hermann},
136	  journal = {Journal of Clinical Epidemiology},
137	  volume  = {46},
138	  number  = {1},
139	  pages   = {57--63},
140	  year    = {1993},
141	  doi     = {10.1016/0895-4356(93)90009-P},
142	}
143	
144	@article{veirod_laake2001,
145	  title   = {Exposure Misclassification: Bias in Category Specific {P}oisson Regression Coefficients},
146	  author  = {Veier{\o}d, Marit B. and Laake, Petter},
147	  journal = {Statistics in Medicine},
148	  volume  = {20},
149	  number  = {5},
150	  pages   = {771--784},
151	  year    = {2001},
152	  doi     = {10.1002/sim.712},
153	}
154	
155	@article{baumann2025,
156	  title   = {Large Language Model Hacking: Quantifying the Hidden Risks of Using {LLM}s for Text Annotation},
157	  author  = {Baumann, Maximilian and R{\"o}ttger, Paul and Urman, Aleksandra and Wendsj{\"o}, Sina and Plaza-del-Arco, Flor Miriam and Gruber, Nora and Hovy, Dirk},
158	  journal = {arXiv preprint arXiv:2509.08825},
159	  year    = {2025},
160	  note    = {Preprint},
161	}
162	
163	@inproceedings{lee_wood_doughty2024,
164	  title     = {Controlling for Unobserved Confounding with Large Language Model Classification of Patient Smoking Status},
165	  author    = {Lee, Samuel and Wood-Doughty, Zach},
166	  booktitle = {AIM-FM Workshop, NeurIPS 2024},
167	  year      = {2024},
168	  note      = {Workshop paper},
169	}
170	
171	@inproceedings{gligoric2025,
172	  title     = {Can Unconfident {LLM} Annotations Be Used for Confident Conclusions?},
173	  author    = {Gligori{\'c}, Kristina and Zrni{\'c}, Tijana and Lee, Sara Y. and Cand{\`e}s, Emmanuel J. and Jurafsky, Dan},
174	  booktitle = {Proceedings of the 2025 Conference of the North American Chapter of the Association for Computational Linguistics},
175	  year      = {2025},
176	}
177	
178	
179	@inproceedings{kim_garg2025,
180	  title     = {Correlated Errors in Large Language Models},
181	  author    = {Kim, Junsol and Garg, Siddharth and Peng, Yuxiao and Garg, Nikhil},
182	  booktitle = {Proceedings of the 42nd International Conference on Machine Learning},
183	  year      = {2025},
184	}
185	
186	@inproceedings{keith_jensen_oconnor2020,
187	  title     = {Text and Causal Inference: A Review of Using Text to Remove Confounding from Causal Estimates},
188	  author    = {Keith, Katherine A. and Jensen, David D. and O'Connor, Brendan T.},
189	  booktitle = {Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},
190	  year      = {2020},
191	  doi       = {10.18653/v1/2020.acl-main.474},
192	}
193	
194	
195	% ── measurement-error-epidemiology (gap-fill) ──
196	
197	@article{ogburn_vanderweele2012,
198	  title   = {On the Nondifferential Misclassification of a Binary Confounder},
199	  author  = {Ogburn, Elizabeth L. and VanderWeele, Tyler J.},
200	  journal = {Epidemiology},
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "198b8b18-46a9-404a-999b-f10be92b3751",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "c9d86249-5c7b-482e-9434-74527708c293",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/references.bib",
      "content": "% Auto-generated from literature_map.yaml — all verified=true entries\n% Last sync: 2026-05-20\n\n@article{cinelli2020making,\n  author    = {Cinelli, Carlos and Hazlett, Chad},\n  title     = {Making Sense of Sensitivity: Extending Omitted Variable Bias},\n  journal   = {Journal of the Royal Statistical Society: Series B (Statistical Methodology)},\n  year      = {2020},\n  volume    = {82},\n  number    = {1},\n  pages     = {39--67},\n  doi       = {10.1111/rssb.12348},\n}\n\n@article{gilardi2023chatgpt,\n  author    = {Gilardi, Fabrizio and Alizadeh, Meysam and Kubli, Ma\\\"{e}l},\n  title     = {{ChatGPT} Outperforms Crowd Workers for Text-Annotation Tasks},\n  journal   = {Proceedings of the National Academy of Sciences},\n  year      = {2023},\n  volume    = {120},\n  number    = {30},\n  pages     = {e2305016120},\n  doi       = {10.1073/pnas.2305016120},\n}\n\n@article{ziems2024can,\n  author    = {Ziems, Caleb and Held, William and Shaikh, Omar and Chen, Jiaao and Zhang, Zhehao and Yang, Diyi},\n  title     = {Can Large Language Models Transform Computational Social Science?},\n  journal   = {Computational Linguistics},\n  year      = {2024},\n  volume    = {50},\n  number    = {1},\n  pages     = {237--291},\n  doi       = {10.1162/coli\\_a\\_00502},\n}\n\n@incollection{bound2001measurement,\n  author    = {Bound, John and Brown, Charles and Mathiowetz, Nancy},\n  title     = {Measurement Error in Survey Data},\n  booktitle = {Handbook of Econometrics},\n  editor    = {Heckman, James J. and Leamer, Edward E.},\n  year      = {2001},\n  volume    = {5},\n  chapter   = {59},\n  pages     = {3705--3843},\n  publisher = {Elsevier},\n}\n\n@article{richardson1993bayesian,\n  author    = {Richardson, Sylvia and Gilks, Walter R.},\n  title     = {A {Bayesian} Approach to Measurement Error Problems in Epidemiology Using Conditional Independence Models},\n  journal   = {American Journal of Epidemiology},\n  year      = {1993},\n  volume    = {138},\n  number    = {6},\n  pages     = {430--442},\n  doi       = {10.1093/oxfordjournals.aje.a116875},\n}\n\n@article{lovell1963,\n  author  = {Lovell, Michael C.},\n  title   = {Seasonal Adjustment of Economic Time Series and Multiple Regression Analysis},\n  journal = {Journal of the American Statistical Association},\n  year    = {1963},\n  volume  = {58},\n  number  = {304},\n  pages   = {993--1010},\n}\n\n@inproceedings{wood_doughty2018,\n  title     = {Challenges of Using Text Classifiers for Causal Inference},\n  author    = {Wood-Doughty, Zach and Shpitser, Ilya and Dredze, Mark},\n  booktitle = {Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing},\n  year      = {2018},\n  doi       = {10.18653/v1/D18-1488},\n}\n\n@article{teblunthuis2024,\n  title   = {Misclassification in Automated Content Analysis Causes Bias in Regression. {C}an We Fix It? {Y}es We Can!},\n  author  = {TeBlunthuis, Nathan and Hase, Valerie and Chan, Chung-hong},\n  journal = {Communication Methods and Measures},\n  volume  = {18},\n  number  = {3},\n  pages   = {278--299},\n  year    = {2024},\n  doi     = {10.1080/19312458.2023.2293713},\n}\n\n@article{hernan_cole2009,\n  title   = {Invited Commentary: Causal Diagrams and Measurement Bias},\n  author  = {Hern{\\'a}n, Miguel A. and Cole, Stephen R.},\n  journal = {American Journal of Epidemiology},\n  volume  = {170},\n  number  = {8},\n  pages   = {959--962},\n  year    = {2009},\n  doi     = {10.1093/aje/kwp293},\n}\n\n\n@article{vanderweele_ding2017,\n  title   = {Sensitivity Analysis in Observational Research: Introducing the {E}-Value},\n  author  = {VanderWeele, Tyler J. and Ding, Peng},\n  journal = {Annals of Internal Medicine},\n  volume  = {167},\n  pages   = {268--274},\n  year    = {2017},\n  doi     = {10.7326/M16-2607},\n}\n\n@article{imai_keele_yamamoto2010,\n  title   = {Identification, Inference and Sensitivity Analysis for Causal Mediation Effects},\n  author  = {Imai, Kosuke and Keele, Luke and Yamamoto, Teppei},\n  journal = {Statistical Science},\n  volume  = {25},\n  number  = {1},\n  pages   = {51--71},\n  year    = {2010},\n  doi     = {10.1214/10-STS321},\n}\n\n@article{valeri_vanderweele2013,\n  title   = {Mediation Analysis Allowing for Exposure-Mediator Interactions and Causal Interpretation: Theoretical Assumptions and Implementation with {SAS} and {SPSS} Macros},\n  author  = {Valeri, Linda and VanderWeele, Tyler J.},\n  journal = {Psychological Methods},\n  volume  = {18},\n  number  = {2},\n  pages   = {137--150},\n  year    = {2013},\n  doi     = {10.1037/a0031034},\n}\n\n@article{brenner1993,\n  title   = {Bias Due to Non-differential Misclassification of Polytomous Confounders},\n  author  = {Brenner, Hermann},\n  journal = {Journal of Clinical Epidemiology},\n  volume  = {46},\n  number  = {1},\n  pages   = {57--63},\n  year    = {1993},\n  doi     = {10.1016/0895-4356(93)90009-P},\n}\n\n@article{veirod_laake2001,\n  title   = {Exposure Misclassification: Bias in Category Specific {P}oisson Regression Coefficients},\n  author  = {Veier{\\o}d, Marit B. and Laake, Petter},\n  journal = {Statistics in Medicine},\n  volume  = {20},\n  number  = {5},\n  pages   = {771--784},\n  year    = {2001},\n  doi     = {10.1002/sim.712},\n}\n\n@article{baumann2025,\n  title   = {Large Language Model Hacking: Quantifying the Hidden Risks of Using {LLM}s for Text Annotation},\n  author  = {Baumann, Maximilian and R{\\\"o}ttger, Paul and Urman, Aleksandra and Wendsj{\\\"o}, Sina and Plaza-del-Arco, Flor Miriam and Gruber, Nora and Hovy, Dirk},\n  journal = {arXiv preprint arXiv:2509.08825},\n  year    = {2025},\n  note    = {Preprint},\n}\n\n@inproceedings{lee_wood_doughty2024,\n  title     = {Controlling for Unobserved Confounding with Large Language Model Classification of Patient Smoking Status},\n  author    = {Lee, Samuel and Wood-Doughty, Zach},\n  booktitle = {AIM-FM Workshop, NeurIPS 2024},\n  year      = {2024},\n  note      = {Workshop paper},\n}\n\n@inproceedings{gligoric2025,\n  title     = {Can Unconfident {LLM} Annotations Be Used for Confident Conclusions?},\n  author    = {Gligori{\\'c}, Kristina and Zrni{\\'c}, Tijana and Lee, Sara Y. and Cand{\\`e}s, Emmanuel J. and Jurafsky, Dan},\n  booktitle = {Proceedings of the 2025 Conference of the North American Chapter of the Association for Computational Linguistics},\n  year      = {2025},\n}\n\n\n@inproceedings{kim_garg2025,\n  title     = {Correlated Errors in Large Language Models},\n  author    = {Kim, Junsol and Garg, Siddharth and Peng, Yuxiao and Garg, Nikhil},\n  booktitle = {Proceedings of the 42nd International Conference on Machine Learning},\n  year      = {2025},\n}\n\n@inproceedings{keith_jensen_oconnor2020,\n  title     = {Text and Causal Inference: A Review of Using Text to Remove Confounding from Causal Estimates},\n  author    = {Keith, Katherine A. and Jensen, David D. and O'Connor, Brendan T.},\n  booktitle = {Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},\n  year      = {2020},\n  doi       = {10.18653/v1/2020.acl-main.474},\n}\n\n\n% ── measurement-error-epidemiology (gap-fill) ──\n\n@article{ogburn_vanderweele2012,\n  title   = {On the Nondifferential Misclassification of a Binary Confounder},\n  author  = {Ogburn, Elizabeth L. and VanderWeele, Tyler J.},\n  journal = {Epidemiology},",
      "numLines": 200,
      "startLine": 1,
      "totalLines": 401
    }
  },
  "sourceToolAssistantUUID": "198b8b18-46a9-404a-999b-f10be92b3751",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 53 · 2026-05-22T16:55:30.562Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01TKS9uwsB5agMYB9LBEJ6JD`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__pdf_to_images",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c9d86249-5c7b-482e-9434-74527708c293",
  "isSidechain": false,
  "requestId": "req_011CbHxYHaDaqm8D22AhwYbs",
  "type": "assistant",
  "uuid": "ffe362d4-526d-4d22-b025-18a8cb888b47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0116MveyYTvMLtaxBus6GoFW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8914,
      "cache_read_input_tokens": 68610,
      "output_tokens": 244,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8914,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 244,
          "cache_read_input_tokens": 68610,
          "cache_creation_input_tokens": 8914,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8914
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

_source line 54 · 2026-05-22T16:55:34.330Z_

让我查看 PDF 渲染结果以确认页数和排版。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cb75bb77-c81e-4917-ab9d-5b6c59359eec",
  "isSidechain": false,
  "requestId": "req_011CbHxYj87fiLrGBfFxfXKL",
  "type": "assistant",
  "uuid": "b24f6269-cf9f-4479-9781-90dec26cf08f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016zdQnVinJx9inzGq3XN5GW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4073,
      "cache_read_input_tokens": 77524,
      "output_tokens": 191,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4073,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 191,
          "cache_read_input_tokens": 77524,
          "cache_creation_input_tokens": 4073,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4073
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

_source line 55 · 2026-05-22T16:55:35.581Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01HyT4RuqY8LeHyyzdqGcmQj`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/submitted.pdf",
  "project": "causal_annot_error_attrib",
  "pages": "1-8",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b24f6269-cf9f-4479-9781-90dec26cf08f",
  "isSidechain": false,
  "requestId": "req_011CbHxYj87fiLrGBfFxfXKL",
  "type": "assistant",
  "uuid": "be308b88-a041-41f5-a905-c37aead3d0d7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016zdQnVinJx9inzGq3XN5GW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4073,
      "cache_read_input_tokens": 77524,
      "output_tokens": 191,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4073,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 191,
          "cache_read_input_tokens": 77524,
          "cache_creation_input_tokens": 4073,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4073
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

_source line 56 · 2026-05-22T16:55:41.643Z_

<details><summary>↩ Tool result · `toolu_01HyT4RuqY8LeHyyzdqGcmQj`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"images\": [{\"page\": 1, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p1.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 432.8}, {\"page\": 2, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p2.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 506.1}, {\"page\": 3, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p3.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 487.2}, {\"page\": 4, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p4.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 502.7}, {\"page\": 5, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p5.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 496.7}, {\"page\": 6, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p6.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 390.4}, {\"page\": 7, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p7.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 490.8}, {\"page\": 8, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p8.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 456.7}], \"total_pages\": 25, \"rendered_pages\": 8, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "be308b88-a041-41f5-a905-c37aead3d0d7",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "959374af-86fb-4b86-83ee-88c7a9da9010",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"images\\\": [{\\\"page\\\": 1, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p1.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 432.8}, {\\\"page\\\": 2, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p2.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 506.1}, {\\\"page\\\": 3, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p3.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 487.2}, {\\\"page\\\": 4, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p4.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 502.7}, {\\\"page\\\": 5, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p5.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 496.7}, {\\\"page\\\": 6, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p6.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 390.4}, {\\\"page\\\": 7, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p7.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 490.8}, {\\\"page\\\": 8, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p8.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 456.7}], \\\"total_pages\\\": 25, \\\"rendered_pages\\\": 8, \\\"dpi\\\": 150, \\\"output_dir\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"images\": [{\"page\": 1, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p1.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 432.8}, {\"page\": 2, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p2.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 506.1}, {\"page\": 3, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p3.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 487.2}, {\"page\": 4, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p4.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 502.7}, {\"page\": 5, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p5.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 496.7}, {\"page\": 6, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p6.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 390.4}, {\"page\": 7, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p7.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 490.8}, {\"page\": 8, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p8.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 456.7}], \"total_pages\": 25, \"rendered_pages\": 8, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "be308b88-a041-41f5-a905-c37aead3d0d7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 57_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "959374af-86fb-4b86-83ee-88c7a9da9010",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Assistant

_source line 58 · 2026-05-22T16:55:44.531Z_

<details><summary>Logged reasoning block</summary>

```text
PDF has 25 pages total. Let me check pages 8-9 to see where the main text ends and references/appendix begin.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "959374af-86fb-4b86-83ee-88c7a9da9010",
  "isSidechain": false,
  "requestId": "req_011CbHxZYBaUzwL1mrxVY2wA",
  "type": "assistant",
  "uuid": "13776b3f-2eaf-4f89-8bd2-702a2436f2c4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187cnr2iZfwLuLF8Ku7c1Bb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 81597,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 81597,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
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

_source line 59 · 2026-05-22T16:55:45.034Z_

PDF 共 25 页。让我看一下第 8-9 页确认正文结束位置。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "13776b3f-2eaf-4f89-8bd2-702a2436f2c4",
  "isSidechain": false,
  "requestId": "req_011CbHxZYBaUzwL1mrxVY2wA",
  "type": "assistant",
  "uuid": "27718e56-b9d1-44f9-94a9-7f79613d8021",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187cnr2iZfwLuLF8Ku7c1Bb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 81597,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 81597,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
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

_source line 60 · 2026-05-22T16:55:46.021Z_

<details open><summary>🔧 Tool call — Read · `toolu_014r9iJVgiQZ3urijrBjtYnT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p7.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "27718e56-b9d1-44f9-94a9-7f79613d8021",
  "isSidechain": false,
  "requestId": "req_011CbHxZYBaUzwL1mrxVY2wA",
  "type": "assistant",
  "uuid": "c9455027-07c6-4220-bc60-ed45d0cabe97",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187cnr2iZfwLuLF8Ku7c1Bb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 81597,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 81597,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
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

_source line 61 · 2026-05-22T16:55:47.600Z_

<details open><summary>🔧 Tool call — Read · `toolu_01YRZq2gR7FzSQnGosyUrwxg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p8.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c9455027-07c6-4220-bc60-ed45d0cabe97",
  "isSidechain": false,
  "requestId": "req_011CbHxZYBaUzwL1mrxVY2wA",
  "type": "assistant",
  "uuid": "ad0d08d4-3f4a-4434-b06e-461dca002914",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187cnr2iZfwLuLF8Ku7c1Bb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 81597,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 81597,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
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

_source line 62 · 2026-05-22T16:55:47.618Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01S1LxoGiPJGrNz5NdZ8AtaY`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/submitted.pdf",
  "project": "causal_annot_error_attrib",
  "pages": "9-10",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ad0d08d4-3f4a-4434-b06e-461dca002914",
  "isSidechain": false,
  "requestId": "req_011CbHxZYBaUzwL1mrxVY2wA",
  "type": "assistant",
  "uuid": "00f7b8df-846e-4387-967d-981cfc3a4368",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187cnr2iZfwLuLF8Ku7c1Bb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 81597,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 81597,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
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

_source line 63 · 2026-05-22T16:55:52.315Z_

<details><summary>↩ Tool result · `toolu_014r9iJVgiQZ3urijrBjtYnT`</summary>

````text
```json
{
  "type": "image",
  "source": {
    "type": "base64",
    "data": "[ATTACHMENT_DATA_REDACTED]",
    "media_type": "image/jpeg"
  }
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c9455027-07c6-4220-bc60-ed45d0cabe97",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "079409a7-b353-4281-82b4-064961b89c66",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 502569
    }
  },
  "sourceToolAssistantUUID": "c9455027-07c6-4220-bc60-ed45d0cabe97",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 64_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "079409a7-b353-4281-82b4-064961b89c66",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Tool result

_source line 65 · 2026-05-22T16:55:53.675Z_

<details><summary>↩ Tool result · `toolu_01YRZq2gR7FzSQnGosyUrwxg`</summary>

````text
```json
{
  "type": "image",
  "source": {
    "type": "base64",
    "data": "[ATTACHMENT_DATA_REDACTED]",
    "media_type": "image/jpeg"
  }
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ad0d08d4-3f4a-4434-b06e-461dca002914",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "b6aedeff-99cb-442d-b328-99020a806955",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 467630
    }
  },
  "sourceToolAssistantUUID": "ad0d08d4-3f4a-4434-b06e-461dca002914",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 66_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "b6aedeff-99cb-442d-b328-99020a806955",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Tool result

_source line 67 · 2026-05-22T16:55:55.526Z_

<details><summary>↩ Tool result · `toolu_01S1LxoGiPJGrNz5NdZ8AtaY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"images\": [{\"page\": 9, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p9.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 534.8}, {\"page\": 10, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p10.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 520.7}], \"total_pages\": 25, \"rendered_pages\": 2, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "00f7b8df-846e-4387-967d-981cfc3a4368",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "7cd3be87-ab83-4113-95bc-e18ac80465b4",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"images\\\": [{\\\"page\\\": 9, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p9.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 534.8}, {\\\"page\\\": 10, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p10.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 520.7}], \\\"total_pages\\\": 25, \\\"rendered_pages\\\": 2, \\\"dpi\\\": 150, \\\"output_dir\\\": \\\"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"images\": [{\"page\": 9, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p9.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 534.8}, {\"page\": 10, \"path\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p10.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 520.7}], \"total_pages\": 25, \"rendered_pages\": 2, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "00f7b8df-846e-4387-967d-981cfc3a4368",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 68 · 2026-05-22T16:55:55.591Z_

```json
{
  "parentUuid": "7cd3be87-ab83-4113-95bc-e18ac80465b4",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "75dcc254-5a0a-45c4-a1a5-8d89b2cbf131",
  "timestamp": "2026-05-22T16:55:55.591Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Tool call

_source line 69 · 2026-05-22T16:55:58.736Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CgvWxmvD45o36ntJZRyKst`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/review_round_5/_pdf_images/submitted_p9.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "75dcc254-5a0a-45c4-a1a5-8d89b2cbf131",
  "isSidechain": false,
  "requestId": "req_011CbHxaZxmG9fEcUc8RU9Ku",
  "type": "assistant",
  "uuid": "5e879013-564a-4bb4-8e78-13898280355e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PzW4w2pMZ2hyV7NXmVFh2H",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1608,
      "cache_read_input_tokens": 82621,
      "output_tokens": 99,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1608,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 99,
          "cache_read_input_tokens": 82621,
          "cache_creation_input_tokens": 1608,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1608
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

_source line 70 · 2026-05-22T16:56:03.394Z_

<details><summary>↩ Tool result · `toolu_01CgvWxmvD45o36ntJZRyKst`</summary>

````text
```json
{
  "type": "image",
  "source": {
    "type": "base64",
    "data": "[ATTACHMENT_DATA_REDACTED]",
    "media_type": "image/jpeg"
  }
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5e879013-564a-4bb4-8e78-13898280355e",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "fcfb3bde-6b36-46d5-be6f-c41298ba8c00",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 547683
    }
  },
  "sourceToolAssistantUUID": "5e879013-564a-4bb4-8e78-13898280355e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 71_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "fcfb3bde-6b36-46d5-be6f-c41298ba8c00",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Assistant

_source line 72 · 2026-05-22T16:59:07.525Z_

<details><summary>Logged reasoning block</summary>

```text
Good. So the paper structure is:
- Pages 1-8: Main text (including Conclusion on p8, Limitations on p8)
- Page 9: References begin
- Pages 9+: References and then Appendix

The main text fits within the 8-page limit. Conclusion and Limitations are on page 8, which is fine since Limitations don't count toward the page limit. Let me verify by looking more carefully at page 8 - the Conclusion section (Section 5) starts in the middle of page 8, and Limitations starts below it on the same page. The actual main text content (Sections 1-5) fits within 8 pages, so that's compliant.


Now I'm compiling my full review of the paper. I've gone through it thoroughly and want to organize my assessment. The work examines how multi-class annotation errors from LLMs propagate through causal inference across seven canonical DAG topologies, deriving bias expressions and proving that matrix-based corrections fail for four topologies via FWL invariance. The paper tackles a practically relevant problem with a novel topology-dependent framing.

What stands out are the strengths: the systematic treatment of seven DAGs goes well beyond prior work, the theoretical proofs around confounding and collider sign preservation are clean and elegant, and the paper is transparent about distinguishing analytical proofs from numerical verification and conjectures. The correction algorithm and ASV framework offer actionable guidance, and the empirical validation across 23 configurations with real LLM confusion matrices grounds everything in practice.

Now I'm moving into the critical assessment of the weaknesses.

The first major issue is that sign preservation for confounding isn't unconditional—Proposition 1(a) only guarantees it when sign(τ) = sign(τ + B_OV), which is a condition on the DGP parameters. The paper presents this in Table 1 with checkmarks as if it's always true, but the main text doesn't adequately flag that this guarantee is conditional, even though the appendix does acknowledge it.

The second issue is more subtle: for confounding, once the DGP condition holds, sign preservation is guaranteed for all values of C, whereas for exposure, no DGP condition can prevent sign reversal when C_kk > 0.5. So confounding and exposure have fundamentally different structures—confounding's sign preservation is conditional on the DGP but then universal across C, while exposure's sign reversal is unconditional on the DGP.

Now I'm looking at Theorem 1 and whether the proof of envelope monotonicity actually holds for general K. The direct argument works for K=2, but...

Actually, I need to be more careful here. The theorem statement claims monotonic non-decreasing behavior, which should be a proved result, not a numerical observation. But the proof only directly establishes this for K=2 through differentiation. For general K, they've only verified it numerically across thousands of random matrices—that's verification, not proof. This is a genuine gap between what's claimed as a theorem and what's actually proved. The core issue is that for K≥3, the paper claims the linear interpolation C(δ) = (1-δ)I + δC_0 makes V_B monotonically non-increasing, but this doesn't follow cleanly from standard degradation arguments—the paper itself notes that showing C(δ_2) = M·C(δ_1) for a stochastic matrix M is non-trivial for this specific family, leaving a genuine proof gap for the general case.

Looking at the empirical validation, Table 7 reveals that Conjecture 1 is violated in 60-97% of matrices across most topologies, which is substantial even if the paper argues the violation magnitudes are small—calling this "ε-approximately monotonic" when the vast majority of cases violate strict monotonicity seems like a stretch.

Examining Table 8 more carefully, I notice the ε bounds are actually exceeded in several cases: confounding and mediation at τ=0.1 show violations around 0.11-0.13, and front-door at τ=5 reaches 0.139, which contradicts the stated bound of ε < 0.06. The Conjecture text specifies front-door is ε-approximately non-decreasing with ε < 0.06 for τ ≤ 2.0, but this qualification isn't clearly stated upfront, and the violations at larger τ values suggest the bounds don't hold uniformly across the parameter space.

For mediation, the paper proves monotonicity under proportional effects and documents small-τ sensitivity in the appendix, so the Conjecture is reasonably well-qualified overall. The real concern is whether "ε-approximately monotonic" remains a useful concept when violations occur this frequently, even if they're small in magnitude—this feels more like a MAJOR issue than CRITICAL.

Now looking at the non-differential misclassification assumption, the paper acknowledges this limitation but doesn't adequately address how realistic it is for LLM annotation, especially since modern LLMs often exhibit differential error patterns depending on the input characteristics. strategies that include context, few-shot examples, and chain-of-thought reasoning that might encode outcome information. The stress test (Appendix B.8) only tests mild violations (ε ≤ 0.10) on the exposure topology, and the extended test only covers 4 topologies. This is an important limitation given that the entire framework rests on this assumption.

Actually, the extended stress test does cover 4 topologies × 2 K × 3 CM qualities × 4 ε = 96 configurations, which is fairly comprehensive. And the result is positive: even at ε=0.10, violations increase by only 7.6 percentage points. So the framework is somewhat robust to violations. Still, the theoretical results don't hold under differential misclassification, which is a limitation.

**M2: Linear SEM assumption**
The paper derives all results under linear structural equations. The nonlinearity check in Appendix B.9 is quite limited—just K=3 with VAST confusion matrices and N=10,000—so it doesn't really test the robustness broadly. The FWL invariance result fundamentally depends on linearity, and in nonlinear settings that column space argument falls apart entirely. The paper acknowledges this in Algorithm 1's caption but doesn't explore what this means for the main findings.

**M3: The 100,000 Dirichlet(1,1,1) sampling**
Using a flat Dirichlet prior over all stochastic matrices casts an extremely wide net and includes many degenerate cases that wouldn't occur in real data. The paper does show results for diagonal ≥ 0.7 subspaces to address this, but the headline numbers like 83.4% sign reversal and 52.6% are based on this very broad sampling scheme.

Actually, I'm noticing the paper does emphasize the diagonal ≥ 0.7 results quite prominently in Section 4.2 and even mentions them in the abstract. So this concern is actually addressed well. I should downgrade this to minor.

**M4: Theory-MC agreement metric**
MAPE of 2.0% looks solid on the surface, but MAPE has a known weakness when true values hover near zero, which can happen depending on the topology and configuration. The per-topology breakdown shows MAPE ranging from 0.5% to 5.5%, with IV having higher error rates in some cases.

I'm realizing I should look more carefully at what's driving these differences across topologies. The variation might be systematic rather than random noise, which would be important to understand.

The paper's treatment of the Dirichlet prior is actually more nuanced than I initially thought—the diagonal ≥ 0.7 constraint is front and center in the main narrative, not buried. The MAPE metric does have limitations near zero values, but the per-topology reporting gives enough transparency that readers can assess the variation themselves. These feel like minor issues rather than major ones.

**M5: Empirical validation uses synthetic DGP with real confusion matrices**
The validation approach in Section 4.4 combines real LLM confusion matrices with synthetic data-generating processes, which doesn't fully test whether the framework works in a completely real-world scenario. The ClinicalBERT case study in Appendix B.7 is more qualitative and retrospective. A stronger validation would involve an actual causal study where ground truth is known.

But this hybrid approach is pretty standard in the measurement error literature, and it's actually quite practical for this kind of work.

So here are the critical issues I'm seeing:

**[CRITICAL] Theorem 1 proof gap for K ≥ 3**: The theorem claims monotonicity holds generally, but the proof only covers K=2. For larger K, the crucial step about V_B(δ) being non-increasing is only verified numerically. This needs to either be stated as a conjecture for K ≥ 3 or the proof needs to be completed.

**[MAJOR] Table 1 overstates unconditional sign preservation**: The checkmarks for confounding, mediation, front-door, and M-bias all depend on specific DGP conditions that aren't clearly stated in the table.

Actually, thinking through this more carefully—the paper frames these as "structural" guarantees depending on topology, but that's still misleading. For confounding, the guarantee only holds if sign(τ) = sign(τ + B_OV). The checkmark suggests the guarantee holds unconditionally, when really it's conditional on DGP parameters. Though I should note that once your DGP satisfies these conditions, the guarantee does hold for all confusion matrices, which is fundamentally different from the exposure case where no DGP condition helps. Let me reconsider whether the paper's framing is actually fair here...

The real distinction is that for these five topologies, sign preservation is a DGP property independent of C, whereas for exposure and IV, sign reversal can occur regardless of DGP parameters. That's a meaningful structural difference, so I'll mark this as [MAJOR] rather than [CRITICAL]—the table just needs clearer explanation of what the conditions actually are.

Now looking at Conjecture 1's violation rates: 60-97% of matrices show non-monotonic steps, and the paper claims ε-approximate monotonicity but Table 8 shows cases where ε reaches 0.06, 0.13, or even 0.15. Since the ASV framework depends on monotonicity, these larger violations could seriously undermine the validity of the thresholds.

The paper does provide a bound: when monotonicity only holds approximately, the reported δ* differs from the true threshold by at most ε/η in δ-units, which they claim is negligible at η = 10%. But working through the math—if ε = 0.13 and η = 0.1, that's an error of 1.3 δ-units, which is actually substantial given that the typical ASV range spans 0-2. So this error could genuinely compromise the reliability of the ASV estimates.

However, these problematic ε values only appear at extreme τ values like 0.1 or 5.0, which the paper identifies as artifacts of small-τ behavior or normalization issues in front-door settings. For the recommended operating range where τ ≥ 0.5, ε stays below 0.06 across most topologies. I'll flag this as a major concern and recommend the paper clearly specify the valid operating range for ASV.

Now I'm revisiting the completeness of Theorem 1's proof. The statement claims that for confounding and mediation topologies with proportional effects, |B(C(δ))| is monotonically non-decreasing in δ across [0, δ_max], and the proof hinges on V_B(δ) being non-increasing.

For the proportional case, I'm working through the variance calculation where the conditional expectation of g(A) given the corrupted observation depends on the confusion matrix C(δ) and the prior distribution, then computing how this variance changes with δ.

The expression for V_B(δ) is a rational function in δ, and while I can derive the derivative analytically for K=2, higher dimensions become algebraically complex. The paper's verification approach seems to involve symbolic computation for small cases and numerical confirmation, though the appendix suggests they may have found a direct argument for the monotonic decrease without fully factorizing the confusion matrix.

Looking more carefully at what they actually proved: for K=2 they have an analytical proof via differentiation, but for general K they only verified numerically across 10,000 random test matrices with no counterexamples. This is a significant gap—the theorem is stated without qualification, but the proof for K≥3 is incomplete. I should flag this as a critical issue since it's presented as a foundational theorem rather than a conjecture, and the ASV framework depends on it. The proof could potentially be completed by leveraging the specific structure of the rational function, but as it stands, the result shouldn't be labeled as a full Theorem—maybe "Theorem (K=2) / Proposition (K≥3 under numerical verification)" would be more honest, or the proof should explicitly flag where it's incomplete. Now I'm thinking through what references might be missing, particularly work on instrumental variable estimation with measurement error, like the Bound, Jaeger, Baker paper on weak instruments. The references seem fairly complete for what the paper covers, though there's a genuine gap around nonlinear correction methods like EM imputation or Bayesian approaches that could potentially circumvent the FWL invariance result—these get mentioned briefly but lack specific citations. Now I'm thinking through what questions to pose to the authors, starting with whether Theorem 1's proof for K=2 can be extended to K≥3 or if the claim should be narrowed, and how practitioners should actually assess the sign preservation conditions in practice when they don't know the true data-generating process.

I'm also wondering whether the claim about same-sign coefficients producing only attenuation can be formalized more rigorously, how sensitive the FWL invariance holds up under nonlinear models beyond the limited logistic check, what minimum fraction of gold labels PPI++ needs to function reliably, and whether the uniform Dirichlet prior could be replaced with something more informed by actual LLM error patterns. The paper does make a solid practical contribution with a well-structured theoretical framework...

The main issues are the incomplete proof of Theorem 1 for K≥3, the conditional nature of the sign preservation guarantees that deserves clearer exposition, uncertainty about whether the non-differential misclassification assumption actually holds for LLMs, and the restrictive linear SEM assumption. But the strengths genuinely outweigh these concerns—the paper introduces a systematic framework that fills a real gap, offers practical tools like ASV for method selection, and backs up its theoretical claims with thorough numerical validation. I'm leaning toward a 3.5-4.0 rating, as this represents a meaningful contribution that bridges NLP and causal inference in a novel way, even if some theoretical results remain incompletely proved.

Assigning scores: Soundness gets 3.5 due to the proof gap and opaque conditional guarantees, Excitement also 3.5 since it's novel and practically useful but somewhat specialized, Overall 3.5 for Borderline Conference, and Confidence 4.0. Though actually, stepping back—the paper has real strengths I should weight more heavily. The taxonomy alone covers seven topologies compared to just one or two in prior work, the FWL invariance negative result is clean and important, the ASV framework is a genuine methodological contribution, and the empirical validation is extensive. The fixable issues with Theorem 1 and the conditional sign preservation don't undermine the core value here. I think this deserves closer to 4.0 for Conference acceptance.

Settling on: Soundness 3.5 (the proof gap matters, some claims need tightening), Excitement 4.0 (novel, systematic, practically relevant), Overall 3.5 (Borderline—accept if Theorem 1 gets addressed), Confidence 4.0. Though I'm second-guessing the excitement rating. For an EMNLP audience specifically, is measurement error in causal inference really exciting? The core is statistics and econometrics applied to LLM annotation—there's no NLP-specific methodology here. A reviewer might see this as less compelling than work directly improving annotation quality or LLM behavior.

But EMNLP does publish at this intersection, and the practical payoff is real: researchers doing causal analysis with LLM annotations need this guidance. The taxonomy of seven topologies is novel and comprehensive, the FWL invariance result is a clean negative finding, and the ASV framework gives actionable direction. The empirical validation backs it up. I think I was being too harsh—this genuinely matters for the community.

The main issues are the proof gap in Theorem 1, the conditionality around sign preservation, and the non-differential assumption, though that last one is standard and the stress tests show it holds up. Looking at the Theorem 1 verification more carefully—they do validate it algebraically and numerically across thousands of configurations with no violations—so while the proof needs tightening, the result itself appears sound. I'm settling on 3.5 overall: solid work that addresses a real problem, but those technical gaps need resolution before I'd fully endorse it for the conference. random C_0 matrices."

The phrase "verified algebraically" is interesting. Maybe they did a symbolic computation for K=3 that they're calling "algebraic"? But the appendix text says "we verify V_B(δ₂) ≤ V_B(δ₁) numerically across all test configurations with zero violations." So "algebraically" might refer to the fact that they compute V_B using exact analytic probability limits (Gauss-Hermite quadrature with 100 points) rather than Monte Carlo samples.

In any case, the Theorem is stated without proof for K ≥ 3, relying on numerical verification. This should be clearly labeled. But the fact that 30,000 configurations show zero violations strongly suggests the result is correct.

Now I'm looking at the empirical scope more carefully—they verify the theory at K=5 and K=7, with main experiments at K=3 (the standard sentiment classification setup), plus validation on K=10 (HumAID) and K=2 (CivilComments). Looking at the Conjecture 1 violation rates in Table 7, most causal structures show high violation counts but with small magnitudes, except for the IV case which has some extreme outliers exceeding 10^6.

The practical question is whether these tiny violations matter for ASV applications, where the threshold is typically 10% of τ and ε < 3% means the optimal δ* shifts by at most 0.3 units—reasonable for real use but worth emphasizing more clearly. The bounds check out: collider and M-bias show worst-case ε of 0.005 and 0.002 respectively, matching the claimed ε < 0.03, though front-door reaches 0.139 at τ=5, exceeding the stated ε < 0.06 bound for τ ≤ 2.0. is a significant issue—the framing suggests monotonicity nearly holds when violations actually occur in 85-97% of cases, just with small magnitudes. I've gathered enough to write a comprehensive review now. My assessment puts this at 3.5/5 across soundness, excitement, and overall merit, landing it as borderline for conference acceptance, with high confidence and reproducibility scores.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fcfb3bde-6b36-46d5-be6f-c41298ba8c00",
  "isSidechain": false,
  "requestId": "req_011CbHxb9KxfuSnDAp6GZghD",
  "type": "assistant",
  "uuid": "a7cafa28-5294-4d25-8198-bb289eec3d5d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q47AwrxhprqLMDk32PztXh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 477,
      "cache_read_input_tokens": 84229,
      "output_tokens": 13656,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 477,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13656,
          "cache_read_input_tokens": 84229,
          "cache_creation_input_tokens": 477,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 477
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

_source line 73 · 2026-05-22T16:59:07.602Z_

论文通读完毕，共 25 页（正文 8 页 + references + appendix），格式合规。现在整理审稿意见并提交。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a7cafa28-5294-4d25-8198-bb289eec3d5d",
  "isSidechain": false,
  "requestId": "req_011CbHxb9KxfuSnDAp6GZghD",
  "type": "assistant",
  "uuid": "e6a1b130-0bf2-412b-8785-d2b099b2a9f3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q47AwrxhprqLMDk32PztXh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 477,
      "cache_read_input_tokens": 84229,
      "output_tokens": 13656,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 477,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13656,
          "cache_read_input_tokens": 84229,
          "cache_creation_input_tokens": 477,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 477
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

_source line 74 · 2026-05-22T17:01:07.733Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01DZMFsNrYGB3v9sebhCWqQF`</summary>

```json
{
  "text": "## Reviewer 1 — Round 1 审稿意见\n\n**论文**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction\n**Venue**: EMNLP 2026 (via ARR)\n**审查侧重**: 方法严谨性 + 实验验证\n\n---\n\n## 总体评分\n**Overall**: 3.5 (Borderline Conference)\n**一句话总结**: 系统性地刻画了 multi-class 标注误差在 7 种 DAG 拓扑下的传播特性，贡献实质性且实用，但 Theorem 1 对 K≥3 的证明依赖数值验证而非解析证明，核心理论主张的严谨性需要加强。\n\n---\n\n## 官方维度打分（ACL ARR review form）\n\n| 维度 | 分数 | 理由摘要 |\n|------|------|----------|\n| Soundness | 3.5/5 | Theorem 1 证明对 K≥3 不完整（仅数值验证）；sign preservation 条件性在 Table 1 中呈现不够透明 |\n| Excitement | 3.5/5 | 问题重要且具实践价值，taxonomy 是首创性工作；但与 NLP community 的核心关注点有一定距离（本质上是统计测量误差理论的应用） |\n| Reproducibility | 4/5 | 承诺开源代码；DGP 参数、采样策略均有详细说明；Appendix 提供了充分的实验细节 |\n| Confidence | 4/5 | 熟悉因果推断和测量误差文献，仔细检查了主要证明 |\n\n---\n\n## 主要优势\n\n**S1. 系统性的拓扑分类学（首创性贡献）。** 现有文献（Teblunthuis 2024 覆盖 4 种二值 DAG；Lee & Wood-Doughty 2024 覆盖 1 种拓扑）均未系统处理 multi-class 情形下 same confusion matrix 在不同 DAG 拓扑下产生质的不同 bias 的问题。本文覆盖 7 种 canonical topology，建立了从 sign-preserving（confounding, collider）到 sign-reversing（exposure, IV）的完整谱系。\n\n**S2. FWL invariance 负结果干净且重要。** 证明 matrix-based corrections 对 4 种 covariate topology 产生 exactly 0% bias reduction（Appendix B.2，基于 column space preservation），这是一个被标注校正文献忽略的重要发现。证明路径（FWL + invertible M preserves column space）简洁完整。\n\n**S3. 三级证据层次结构透明。** 论文诚实地区分了 (i) 解析证明（confounding, collider sign preservation）、(ii) 数值验证零违反（mediation, M-bias, front-door）、(iii) ε-approximate conjecture，这种透明度是值得肯定的。\n\n**S4. 实证验证有说服力。** 23 个真实 LLM configuration × 7 topologies × 3 datasets（HumAID K=10, VAST K=3, CivilComments K=2），覆盖了 frontier 到 7B 模型，结果与理论预测一致。\"Primary coefficient never reverses\" 的经验发现（Section 4.4）具有实践指导意义。\n\n**S5. ASV 框架具有实践价值。** 将 E-value 的思路扩展到标注误差场景，三种 ASV 类型（magnitude, significance, sign-flip）对应不同拓扑的失败模式，加上 Algorithm 1 的 correction routing，为从业者提供了可操作的指导。\n\n---\n\n## Must-Fix 问题（影响接收决定）\n\n**N1** [critical] **Theorem 1 对 K ≥ 3 缺乏解析证明，不应标为 \"Theorem\"**\n- 具体位置：Section 3.3 Theorem 1; Appendix B.2\n- 问题：Theorem 1 声称 confounding 和 mediation（proportional effects）下 |B(C(δ))| 关于 δ 单调不减，但证明的关键步骤——V_B(δ) 关于 δ 单调不增——对 K=2 通过直接求导证明，对 general K 仅通过数值验证（\"verified... numerically across all test configurations with zero violations\"，Appendix B.2 第 243 行）。论文自身承认 \"the exact degradation factorization C(δ₂) = M·C(δ₁) for a stochastic M is non-trivial for the linear interpolation family\"，即关键的信息论退化论证不成立。\n- 为什么影响接收：标为 \"Theorem\" 意味着有完整证明。10,000 个随机矩阵零违反是强数值证据，但不构成证明。ASV 框架的有效性建立在此 monotonicity 上——如果它不成立（即使概率极低），ASV 阈值 δ* 可能不正确。\n- 建议修改方向：(a) 将 K ≥ 3 的声明降级为 Proposition（numerical evidence）或 Conjecture，保留 K=2 作为 Theorem；(b) 或完成 general K 的证明——考虑对 C(δ) 的 rational function structure 进行 symbolic computation（V_B(δ) 是 δ 的有理函数，可以验证其导数符号）；(c) 至少在证明中明确标注 \"For K ≥ 3, this step is verified numerically; a complete analytic proof remains open.\"\n\n**N2** [critical] **Table 1 的 sign-flip guarantee checkmarks 掩盖了 DGP 条件性**\n- 具体位置：Table 1 (Section 4.2); Proposition 1(a) Section 3.2\n- 问题：Table 1 对 confounding, mediation, front-door 标注 ✓（\"structural sign-flip guarantee holds\"），但这些保证都有 DGP 条件：confounding 需要 sign(τ) = sign(τ + B_OV)；mediation 需要 sign(τ_dir) = sign(τ_total)；front-door 需要 sign(λα_U) = sign(λα_U + Cov(T,f(A)))。这些条件在论文的 DGP 参数下成立（Appendix C.1 Table 5），但并非无条件。论文在 Appendix 第 699-703 行讨论了条件失败的情况（\"opposing effects\"），说明反例是存在的。\n- 为什么影响接收：Table 1 是论文最核心的结果汇总表，读者（尤其是 practitioners）会直接查表做决策。✓ 暗示无条件保证，但实际上是有条件的。如果一个 practitioner 的 confounding 场景恰好 sign(τ) ≠ sign(τ + B_OV)（如 suppression 效应），Table 1 的 ✓ 会给出错误的安全感。\n- 建议修改方向：(a) 在 Table 1 中用不同符号区分无条件保证（如 collider 在论文参数下是 |τ| > B̄_col，这也是有条件的）和有条件保证，或加脚注标注条件；(b) 在 caption 中明确 \"✓ indicates sign preservation under DGP-specific sufficient conditions (Table 5 in Appendix); ✗ indicates no such condition exists.\"\n\n---\n\n## Should-Fix 问题（影响评分但不一票否决）\n\n**W1** [major] **Conjecture 1 的 \"ε-approximately monotonic\" 表述可能误导**\n- 具体位置：Conjecture 1 (Section 3.3); Table 7 (Appendix B.12)\n- 问题：Table 7 显示 60-98% 的矩阵存在非单调步骤（如 confounding K=3: 8467/10000，M-bias: 9791/10000）。虽然 worst-case magnitude 很小（非 IV: < 0.056），但 \"ε-approximately monotonic\" 这个术语可能给读者一种\"几乎单调\"的印象，而实际上是\"几乎处处非单调但偏差量级很小\"。此外，Table 8 显示在 τ=0.1（mediation ε=0.130）和 τ=5.0（front-door ε=0.139）时 ε 明显超过 0.06。\n- 建议：(a) 明确 ASV 的推荐适用范围（如 |τ| ≥ 0.5 in standardized units），并在 Conjecture 正文中加入 τ 范围限制；(b) 讨论 ε/η 误差对 δ* 的影响——当 ε=0.13, η=0.10 时，δ* 误差可达 1.3 units，这在 ASV 通常为 0-2 的范围内并非 negligible。\n\n**W2** [major] **Non-differential misclassification 假设在 LLM 场景下需要更充分讨论**\n- 具体位置：Definition 1 (Section 3.1); Limitations (Section 5)\n- 问题：Definition 1 假设 P(A*|A,Y,Z) = P(A*|A)，即 LLM 标注不依赖 outcome。论文在 Limitations 中列举了可能违反的场景（outcome-conditional prompting, few-shot demonstrations encoding outcome associations）。但现代 LLM 标注实践中，prompt 往往包含 context（可能间接包含 Y 信息），RAG 流程可能检索到包含 Y 的文档，chain-of-thought 推理可能利用 Y 相关的先验知识。Appendix B.8 的 stress test 覆盖了 4 topologies 但仅测试 ε ≤ 0.10 的温和违反，且 sign-flip rate 在 ε=0.10 时对 IV（K=3, low-quality CM）达到 7%。\n- 建议：(a) 在 Section 3.1 更充分讨论这一假设何时成立/不成立（不仅在 Limitations 中简述）；(b) 提供一个简单的 diagnostic（如检验 C 在 Y 的不同水平上是否一致）帮助 practitioners 验证该假设。\n\n**W3** [major] **线性 SEM 假设对 FWL invariance 结论的影响讨论不足**\n- 具体位置：Algorithm 1 caption; Appendix B.9\n- 问题：FWL invariance 是论文的核心负结果之一（matrix-based corrections 对 4 种拓扑无效），但它根本性地依赖线性 SEM。在非线性模型（如 logistic regression, probit）中，FWL 不成立，column space argument 失效。Algorithm 1 的 caption 提到 \"FWL-based routing may not apply under nonlinear models\"，但这个 caveat 在正文中没有讨论。Appendix B.9 的 logistic DGP 检查仅测试 sign-flip pattern 是否 preserved，没有直接测试 FWL invariance 是否在 logistic 下打破。\n- 建议：(a) 在 Section 4.5 的 FWL invariance 段落中加入一句话讨论非线性情形；(b) 在 logistic DGP 实验中增加一个 correction experiment，验证 Naive plug-in 在 logistic 下是否仍然 0% reduction。\n\n**W4** [minor] **Exposure topology 的 \"primary coefficient never reverses\" 缺乏理论保证**\n- 具体位置：Section 4.4 第 78 行; Abstract\n- 问题：论文反复强调 \"the primary treatment effect never reverses\" 并在 abstract 中写 \"the primary treatment effect never reverses in any of 23 empirical LLM configurations\"。这是一个经验发现（23 configurations × exposure topology），但论文未给出理论保证。从 Eq.(2) 看，primary coefficient 的 sign preservation 取决于 weights w_jk 的结构——当 primary category 的 w_jk 不将 opposite-sign categories 的权重超过 primary 自身时成立。论文没有证明在什么条件下这一定成立。\n- 建议：(a) 将 abstract 中的措辞改为 conditional（\"In our experiments, the primary...\"）；(b) 如果可能，给出 primary coefficient sign preservation 的充分条件（如 diagonal dominance + primary category 有最大 prevalence）。\n\n**W5** [minor] **Theory-MC agreement 的 MAPE 2.0% 可能掩盖尾部偏差**\n- 具体位置：Section 4.2 第 15 行\n- 问题：Grand MAPE 2.0% across 126 scenarios 是 mean；IV topology 的 MAPE 高达 5.5%。MAPE 对真值接近零的情况敏感（小绝对误差 → 大相对误差）。论文未报告 max absolute error 或 coverage（如 95% MC estimate 落在 analytic plim 的 ±x% 内的比例）。\n- 建议：补充 absolute error 的 median 和 max，或 coverage 统计，特别是对 IV topology。\n\n---\n\n## 小问题（不影响接收）\n\n1. **Section 3.2 Eq.(1)**: 公式用了 Z'Z 但 Z 的定义依赖 A*（dummies of A*），而目标参数 τ 是 X 的系数。公式和文字的 notation 可以更清晰——Z 是否包含 intercept？\n2. **Section 4.2**: \"18 LLM configurations × 7 topologies\" 但 Section 4.4 说 \"23 LLM configurations\"。请确认是 18 还是 23（Theory-MC validation 用了 18？Empirical validation 用了 23？需要说明差异）。\n3. **Table 2 (Appendix)**: ASV 表的 \"Rank\" 列将 exposure 列为 \"---\"，但 exposure 有 sign-flip ASV，在 vulnerability 谱系中应有位置。\n4. **Appendix B.8 Table 4**: ε=0.00 baseline 的 sign-flip rate 是 2.0%，但 Section 4.2 报告 diagonal ≥ 0.7 条件下是 2.1%。差异可能源于采样噪声，但应明确说明。\n5. **Conjecture 1 排除 IV 的理由**: \"the Wald estimator exhibits singularities when the first-stage coefficient passes through zero\"——这本身就是 IV 标注误差危害的一部分，将其排除使 Conjecture 回避了最难的情况。建议明确说明 IV 的 ASV 是如何处理 singularity 的（是否在 singular 附近截断？）。\n6. **References**: Baumann et al. (2025) 标注为 arXiv preprint。如果有正式发表版本应更新。\n\n---\n\n## Questions（需要作者回答）\n\n**Q1.** Theorem 1 对 K ≥ 3 的证明能否完成？V_B(δ) 作为 δ 的有理函数，其分子分母的 degree 有限——是否尝试过对 K=3 进行 symbolic differentiation 并验证导数符号？\n\n**Q2.** Sign preservation 的 DGP 条件（如 sign(τ) = sign(τ + B_OV) for confounding）在实践中如何验证？Practitioner 不知道真实 τ 和 B_OV。论文建议 \"compute ASV under candidate DAGs and report the most conservative\"（Limitations），但这不回答条件验证的问题。\n\n**Q3.** 论文提到 \"same-sign β_k produce only attenuation\" (Section 4.4 第 78 行)。这是否意味着当所有 category 的 treatment effect 同号时，exposure 也有 sign preservation guarantee？如果是，这是一个重要结论，应在正文中 formalize。\n\n**Q4.** PPI++ 需要 gold labels。在 correction experiments 中，gold label 比例是多少？Table 3 报告 47.0% RMSE reduction——这在什么 gold label fraction 下实现？是否有 sensitivity to gold label size 的分析？\n\n**Q5.** FWL invariance 在非线性模型下是否 breakdown？是否可以用 logistic DGP 验证 Naive plug-in 不再是 0% reduction？\n\n**Q6.** Dirichlet(1,1,1) 先验下 83.4% sign reversal 对实际 NLP 研究者意味着什么？如果改用拟合 empirical LLM confusion matrices 的 informative prior（如 Dirichlet(α) with α > 1 集中在 diagonal-dominant 区域），sign reversal rate 会如何变化？\n\n---\n\n## Missing References\n\n1. **Frölich (2007)** \"Nonparametric IV estimation in the presence of endogenous regressors\" 或 **Mahajan (2006)** \"Identification and estimation of regression models with misclassification\" — IV with mismeasured instruments 的理论基础，与 Section 3.2 的 IV topology 直接相关。\n2. **Kang & Schafer (2007)** \"Demystifying Double Robustness\" — doubly robust estimators 可能绕过 FWL invariance 限制，值得在 correction guidance 部分讨论。\n3. 最近的 **Zhang & Spirtes (2024)** 或 **Zhang et al. (2024)** 关于 causal discovery with measurement error 的工作——虽然论文假设 DAG 已知，但讨论 DAG uncertainty 时应引用。\n\n---\n\n## Overall Assessment\n\n**评分: 3.5 (Borderline Conference)**\n**置信度: 4/5**\n\n本文对一个实际重要的问题（LLM 标注误差在因果推断中的传播）做出了系统性贡献。7 种拓扑的 bias taxonomy、FWL invariance 负结果、ASV 框架都是 genuine contributions。经验验证覆盖面广、设计合理。\n\n阻止我给出 4.0 的主要原因是 Theorem 1 的证明完整性问题（N1）：一个标为 Theorem 的核心结果不应依赖数值验证。如果作者能 (a) 完成 K≥3 的证明或 (b) 诚实降级为 numerical result + conjecture，我会上调评分。Table 1 的条件性问题（N2）是 presentation 层面的，修改成本低但影响读者理解。\n\n论文的 excitement 对 EMNLP 来说处于边界——核心是统计测量误差理论，NLP-specific 的贡献在于 empirical validation with real LLM configurations 和 practical guidance。但考虑到 LLM-as-annotator 是 NLP 社区的热点话题，实际影响力不低。",
  "reviewer_id": "1",
  "project": "causal_annot_error_attrib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6a1b130-0bf2-412b-8785-d2b099b2a9f3",
  "isSidechain": false,
  "requestId": "req_011CbHxb9KxfuSnDAp6GZghD",
  "type": "assistant",
  "uuid": "344fb99f-b6f2-42d3-9407-d81c41223f19",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q47AwrxhprqLMDk32PztXh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 477,
      "cache_read_input_tokens": 84229,
      "output_tokens": 13656,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 477,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13656,
          "cache_read_input_tokens": 84229,
          "cache_creation_input_tokens": 477,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 477
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

_source line 75_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **审查侧重：方法严谨性 + 实验验证**  ### 论文信息 - **标题**: Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction - **论文路径…",
  "leafUuid": "344fb99f-b6f2-42d3-9407-d81c41223f19",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Tool result

_source line 76 · 2026-05-22T17:01:18.969Z_

<details><summary>↩ Tool result · `toolu_01DZMFsNrYGB3v9sebhCWqQF`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_9f117624057fcf6cb95db4d67f525246:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "344fb99f-b6f2-42d3-9407-d81c41223f19",
  "isSidechain": false,
  "promptId": "17d61720-c7d9-4b13-9892-27c475c286bb",
  "type": "user",
  "uuid": "33640eb8-cbd6-42b5-980e-3adfd728ebe2",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_9f117624057fcf6cb95db4d67f525246:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_9f117624057fcf6cb95db4d67f525246:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "344fb99f-b6f2-42d3-9407-d81c41223f19",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 77 · 2026-05-22T17:04:22.145Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-22T17:04:22.145Z",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "content": "[Round 1 审稿请求]:\n## 交叉分享 — Reviewer 2 的完整审稿意见\n\n请逐条回应 Reviewer 2 的每个 Weakness/Question，使用 [AGREE] 或 [REBUT] 标记，并提供具体理由（引用论文的 Section/Table/Figure 作为证据）。\n\n---\n\n以下是 Reviewer 2 的完整审稿意见：\n\n### Overall: 3.5 (Borderline Conference)\n\n### Strengths\nS1. 系统性的跨拓扑分析填补明确研究空白（\"首次跨 7 种拓扑系统比较\"经核查成立）\nS2. 理论结果层次化处理体现学术诚实\nS3. FWL 不变性负面结果具有重要实用价值\nS4. 经验验证覆盖面广且设计合理\nS5. ASV 框架是 E-value 的有意义扩展\nS6. 论文整体结构清晰，逻辑流畅\n\n### Weaknesses\n\n**N1 [MAJOR] 非差异性误分类假设在 LLM 场景下适用性存疑**\n- LLM 处理的文本本身同时包含 treatment 和 outcome 信号（如标注情感时文本中有购买行为描述）。Few-shot demonstrations 编码 treatment-outcome 关联。更根本的是\"文本作为共同原因\"导致结构性差异性。Appendix B.5 的 stress test 仅测试人为添加的 ε 参数，未测试 LLM 诱导的真实差异性模式。\n- 建议：讨论\"文本作为共同原因\"机制，提供定性分析。\n\n**N2 [MAJOR] 线性 SEM 的限制性未被充分验证**\n- 所有 bias 表达式基于线性 SEM。logistic DGP 检查仅验证 sign-flip 一致性，未验证偏差量级、ASV 排名、FWL 不变性。FWL 是线性投影性质，非线性模型中 matrix-based corrections 可能有效。\n- 建议：明确 FWL 适用范围限于线性模型；logistic DGP 下验证至少一个拓扑的校正效果。\n\n**N3 [MAJOR] Conjecture 1 呈现方式不够审慎**\n- ε 可达 0.14（front-door）/0.15（exposure），ε/η = 1.4 δ-units 并非 negligible。论文措辞\"negligible\"轻描淡写。\n- 建议：显式标注 ε 范围和条件；用独立段落讨论 ε 对 δ* 精度影响。\n\n**W1 [MINOR] \"Primary coefficient never reverses\" 缺乏理论保证**\n\n**W2 [MINOR] 数字密度较高影响可读性**\n\n**W3 [MINOR] 符号使用存在轻微不一致（τ 在不同拓扑下含义不同）**\n\n**W4 [MINOR] ClinicalBERT 案例研究（Appendix B.3）过于简略**\n\n### Questions\nQ1. \"文本作为共同原因\"导致的差异性误分类如何影响符号保持结论？\nQ2. DGP 参数（τ=2.0）是否代表 CSS 典型效应量？小效应下条件是否更易违反？\nQ3. 候选拓扑含 exposure 和 confounding 时如何定义\"most conservative\" ASV？\nQ4. FWL 不变性在非线性模型下是否成立？\nQ5. Dirichlet(1,1,1) 的 83.4% sign reversal 在现实先验下是否大幅降低？2.1%（diagonal≥0.7）是否更具参考价值？\n\n### Missing References\nM1. Lash, Fox, Fink (2009/2021) — quantitative bias analysis 教科书\nM2. Kuroki & Pearl (2014) — measurement bias and effect restoration\nM3. Mohan, Pearl, Tian (2013) — missing data as causal problem\n\n### 格式合规检查：全部通过（正文≤8页、ACL模板、匿名、Limitations、图表质量）\n\n---\n\n请对以上每个 N/W/Q 逐条给出 [AGREE] 或 [REBUT] 回应。"
}
```

---

### Runtime record

_source line 78 · 2026-05-22T17:04:22.146Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-22T17:04:22.146Z",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

## Round 4

2 recorded events

### User

_source line 79 · 2026-05-22T17:04:22.088Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "33640eb8-cbd6-42b5-980e-3adfd728ebe2",
  "isSidechain": false,
  "promptId": "54df9cb4-68ce-4194-b5e4-49ab7f5b4caf",
  "type": "user",
  "isMeta": true,
  "uuid": "be400d3d-8d88-4533-b866-c08d06f6bd52",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 80 · 2026-05-22T17:04:22.088Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "be400d3d-8d88-4533-b866-c08d06f6bd52",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "3690601e-4eca-4d12-88fa-83f53c07a94d",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "id": "55dbd671-c70d-44ec-8c53-8908f10d4461",
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

## Round 5

7 recorded events

### User

_source line 81 · 2026-05-22T17:04:23.807Z_

[Round 1 审稿请求]:
## 交叉分享 — Reviewer 2 的完整审稿意见

请逐条回应 Reviewer 2 的每个 Weakness/Question，使用 [AGREE] 或 [REBUT] 标记，并提供具体理由（引用论文的 Section/Table/Figure 作为证据）。

---

以下是 Reviewer 2 的完整审稿意见：

### Overall: 3.5 (Borderline Conference)

### Strengths
S1. 系统性的跨拓扑分析填补明确研究空白（"首次跨 7 种拓扑系统比较"经核查成立）
S2. 理论结果层次化处理体现学术诚实
S3. FWL 不变性负面结果具有重要实用价值
S4. 经验验证覆盖面广且设计合理
S5. ASV 框架是 E-value 的有意义扩展
S6. 论文整体结构清晰，逻辑流畅

### Weaknesses

**N1 [MAJOR] 非差异性误分类假设在 LLM 场景下适用性存疑**
- LLM 处理的文本本身同时包含 treatment 和 outcome 信号（如标注情感时文本中有购买行为描述）。Few-shot demonstrations 编码 treatment-outcome 关联。更根本的是"文本作为共同原因"导致结构性差异性。Appendix B.5 的 stress test 仅测试人为添加的 ε 参数，未测试 LLM 诱导的真实差异性模式。
- 建议：讨论"文本作为共同原因"机制，提供定性分析。

**N2 [MAJOR] 线性 SEM 的限制性未被充分验证**
- 所有 bias 表达式基于线性 SEM。logistic DGP 检查仅验证 sign-flip 一致性，未验证偏差量级、ASV 排名、FWL 不变性。FWL 是线性投影性质，非线性模型中 matrix-based corrections 可能有效。
- 建议：明确 FWL 适用范围限于线性模型；logistic DGP 下验证至少一个拓扑的校正效果。

**N3 [MAJOR] Conjecture 1 呈现方式不够审慎**
- ε 可达 0.14（front-door）/0.15（exposure），ε/η = 1.4 δ-units 并非 negligible。论文措辞"negligible"轻描淡写。
- 建议：显式标注 ε 范围和条件；用独立段落讨论 ε 对 δ* 精度影响。

**W1 [MINOR] "Primary coefficient never reverses" 缺乏理论保证**

**W2 [MINOR] 数字密度较高影响可读性**

**W3 [MINOR] 符号使用存在轻微不一致（τ 在不同拓扑下含义不同）**

**W4 [MINOR] ClinicalBERT 案例研究（Appendix B.3）过于简略**

### Questions
Q1. "文本作为共同原因"导致的差异性误分类如何影响符号保持结论？
Q2. DGP 参数（τ=2.0）是否代表 CSS 典型效应量？小效应下条件是否更易违反？
Q3. 候选拓扑含 exposure 和 confounding 时如何定义"most conservative" ASV？
Q4. FWL 不变性在非线性模型下是否成立？
Q5. Dirichlet(1,1,1) 的 83.4% sign reversal 在现实先验下是否大幅降低？2.1%（diagonal≥0.7）是否更具参考价值？

### Missing References
M1. Lash, Fox, Fink (2009/2021) — quantitative bias analysis 教科书
M2. Kuroki & Pearl (2014) — measurement bias and effect restoration
M3. Mohan, Pearl, Tian (2013) — missing data as causal problem

### 格式合规检查：全部通过（正文≤8页、ACL模板、匿名、Limitations、图表质量）

---

请对以上每个 N/W/Q 逐条给出 [AGREE] 或 [REBUT] 回应。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3690601e-4eca-4d12-88fa-83f53c07a94d",
  "isSidechain": false,
  "promptId": "54df9cb4-68ce-4194-b5e4-49ab7f5b4caf",
  "type": "user",
  "uuid": "83d5d832-ac34-4dcf-ace5-285cb41c226a",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 82 · 2026-05-22T17:04:23.807Z_

```json
{
  "parentUuid": "83d5d832-ac34-4dcf-ace5-285cb41c226a",
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
  "uuid": "f869163d-60ce-4b8b-aebb-cf0eb2e73899",
  "timestamp": "2026-05-22T17:04:23.807Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 83 · 2026-05-22T17:05:25.537Z_

<details><summary>Logged reasoning block</summary>

```text
The Director is asking me (Reviewer 1) to cross-review Reviewer 2's findings. I need to go through each Weakness, Question, and Missing Reference from Reviewer 2 and provide [AGREE] or [REBUT] responses with specific evidence from the paper.

Let me carefully consider each point, referencing specific sections/tables/figures from the paper I've already read.

Let me go through each one:

**N1 [MAJOR] Non-differential misclassification assumption in LLM settings**
- R2 raises the "text as common cause" argument: when LLMs annotate text that contains both treatment and outcome signals, the misclassification becomes structurally differential.


- This is a compelling point that the paper's Definition 1 (Section 3.1) doesn't adequately address—it assumes P(A*|A,Y,Z) = P(A*|A), but the stress test in Appendix B.8 only uses artificial perturbations rather than realistic LLM-induced differential patterns. R2's framing is more precise than my own similar concern (W2), so I should [AGREE] here.

- R2 correctly identifies that the logistic DGP check in Appendix B.9 only validates sign-flip consistency, not bias magnitude or FWL invariance under nonlinear models—my W3 raised the same issue. The paper shows SF_τ differences < 0.02 but doesn't verify whether Naive plug-in achieves meaningful bias reduction in logistic regression, which would violate FWL invariance. I should [AGREE] on this overlap.

- R2 points out that ε can reach 0.14-0.15, making the ratio ε/η = 1.4 δ-units non-negligible, and Conjecture 1's presentation isn't cautious enough about this magnitude.
- But looking more carefully, those extreme ε values only occur at the tails (τ=0.1 for mediation, τ=5.0 for front-door). Within the recommended operating range (τ ∈ [0.5, 2.0]), ε stays below 0.06 for most topologies, and the paper does qualify this in the Conjecture text itself.
- I should [AGREE] that the "negligible" claim is misleading when ε can be substantial, but [REBUT] the severity—the paper does provide the τ-range qualifications that contextualize this.

Actually, let me reconsider. R2 and I both flagged this as a major issue, so we're aligned on severity. Looking at the actual numbers from Table 8: front-door reaches ε = 0.139 at τ=5.0, and exposure ranges from 0.111 to 0.152 across different τ values. But the Conjecture text itself acknowledges this—it says ε < 0.06 for τ ≤ 2.0 and notes that at extreme τ values, normalization artifacts can push ε up to about 0.14. For exposure, it mentions ε < 0.008 at the 99th percentile, though extreme-tail matrices make up less than 0.02% of the Dirichlet draws.

So the Conjecture does have these qualifications built in. The real concern is whether readers who don't dig into the fine print will understand the scope of these extreme cases. I'll agree with the core issue but note that the Conjecture itself provides the necessary caveats.

On the coefficient reversal point—I flagged this as minor in my review too, and I agree with that assessment.

The numerical density is a presentation issue, and while it's real, it's somewhat unavoidable given the 8-page limit and the need to cover results across 7 topologies and multiple metrics. I'll mildly agree it's a concern.

For the notation inconsistency, τ does shift meaning across topologies—treatment effect for confounding, direct effect for mediation, LATE for IV. But this is standard practice in the measurement error literature, where each topology has its own target parameter. The paper does define τ generically as "the causal parameter of interest" with topology-specific definitions. There's actually a notation table in Appendix C that covers this, so while a version in the main text would help readability, the definitions are already there. I'll mildly agree on this one.

On the ClinicalBERT case study, Appendix B.7 is brief—about half a page—but it does make three concrete points: the sign-flip guarantee, the FWL invariance warning, and a correction recommendation. For an appendix case study that's reasonable, though adding quantitative ASV computations would definitely strengthen it. I'll mildly agree here too.

For the open questions: the "text as common cause" mechanism and differential misclassification is worth addressing—that ties back to the earlier notation point. On the τ=2.0 parameter choice for the confounding DGP, I need to check whether that's representative of realistic effect sizes.

Looking at the sensitivity analysis in Appendix B.12, the paper tests τ across {0.1, 0.5, 1.0, 2.0, 5.0}, and the sign preservation conditions break down more easily at small τ values. In computational social science, treatment effects are typically small—standardized coefficients in the [0.05, 0.5] range—so τ=2.0 is actually quite large. The condition sign(τ) = sign(τ + B_OV) becomes fragile when |τ| is small relative to |B_OV|, which is the more common regime in CSS. That's a legitimate concern, and I should agree with it.

Now, when candidate DAGs contain both exposure and confounding pathways, defining the "most conservative" ASV becomes tricky. The paper says practitioners should compute ASV under different candidate DAGs and report the most conservative estimate, but if one topology shows the sign is safe while another shows 83.4% sign reversal, reporting the worst case effectively assumes the most pessimistic scenario. This deserves more careful discussion.

The FWL invariance question under nonlinear models aligns with earlier concerns about whether the results hold beyond linear settings. On the Dirichlet(1,1,1) finding showing 83.4% versus 2.1% sign reversal depending on the diagonal threshold—the paper already addresses this in Section 4.2 and the abstract, presenting the 2.1% as the more realistic rate.

Looking back at the abstract, it actually does highlight the 2.1% prominently when discussing realistic LLM accuracy (diagonal ≥ 0.7), while the 83.4% appears more implicitly as a "structural possibility" and more explicitly later in the paper. The Introduction does mention the 83.4% figure more directly, so the framing could be more balanced between these two rates from the start.

For the missing references, Lash, Fox, and Fink's quantitative bias analysis textbook is a standard foundational text in epidemiology that would complement the existing citations like Carroll et al. and Gustafson. It's worth including for applied guidance on bias analysis methods.

Kuroki and Pearl's work on measurement bias and effect restoration is directly relevant to the correction methods the paper discusses, so that should be cited as well. Mohan, Pearl, and Tian's extension of graphical approaches to missing data is somewhat relevant given the paper's use of starred-node DAGs, though it's less critical since related graphical frameworks are already cited.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f869163d-60ce-4b8b-aebb-cf0eb2e73899",
  "isSidechain": false,
  "requestId": "req_011CbHyE2w29EUs1eRViKeU8",
  "type": "assistant",
  "uuid": "d06b9390-b176-4e74-9858-a50b45d89018",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W5h3RwGQiWMZQNijKXFqM6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1336,
      "cache_read_input_tokens": 98428,
      "output_tokens": 6931,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 6931,
          "cache_read_input_tokens": 98428,
          "cache_creation_input_tokens": 1336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1336
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

_source line 84 · 2026-05-22T17:05:25.546Z_

逐条回应 Reviewer 2 的审稿意见。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d06b9390-b176-4e74-9858-a50b45d89018",
  "isSidechain": false,
  "requestId": "req_011CbHyE2w29EUs1eRViKeU8",
  "type": "assistant",
  "uuid": "85696c1e-5ba8-4095-9b49-525c9c4bf108",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W5h3RwGQiWMZQNijKXFqM6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1336,
      "cache_read_input_tokens": 98428,
      "output_tokens": 6931,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 6931,
          "cache_read_input_tokens": 98428,
          "cache_creation_input_tokens": 1336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1336
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

_source line 85 · 2026-05-22T17:06:47.260Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01EAgjSwcr85LUYBT6Cpzt2j`</summary>

```json
{
  "text": "## Reviewer 1 — 交叉回应 Reviewer 2 审稿意见\n\n---\n\n### Weaknesses 逐条回应\n\n**[AGREE] R2-N1: 非差异性误分类假设在 LLM 场景下适用性存疑**\n\n同意这是一个重要问题，且 R2 的 \"文本作为共同原因\" 框架比我自己的 W2 表述更精确。核心论点：LLM 从同一段文本中同时提取 treatment signal 和（间接的）outcome signal，这在结构上违反 Definition 1 的 P(A*|A,Y,Z) = P(A*|A)，不是简单的 \"mild violation\" 而是架构性的。\n\n论文在 Section 3.1 第 14 行提到 \"natural when the LLM annotates treatment labels from source documents without access to outcome information\"，但现代标注场景中文本本身就携带 outcome 信息（如标注政治立场时，文本同时包含投票行为的线索）。Appendix B.8 的 stress test 通过人为添加 ε-perturbation 模拟差异性，但这与 LLM 从文本中提取 outcome-correlated features 的真实模式在结构上不同。\n\n不过我要补充一点 nuance：violation severity 是 topology-dependent 的。Table 4 (Appendix B.8) 显示即使在 ε=0.10 下，exposure sign-flip 仅从 2.0% 升至 4.5%，增幅有限。这说明对大多数 topology，moderate differential misclassification 不会剧烈改变定性结论，虽然 R2 的理论担忧是对的。\n\n**建议给作者的修改优先级：SHOULD-FIX。** 在 Section 3.1 加入 \"text as common cause\" 讨论，但不必重做全部理论（differential misclassification 的完整理论是另一篇论文的工作量）。\n\n---\n\n**[AGREE] R2-N2: 线性 SEM 的限制性未被充分验证**\n\n与我的 W3 完全一致。关键缺口：Appendix B.9 的 logistic DGP 检查仅验证 sign-flip pattern（SF_τ 和 SF_any），但完全没有验证两个核心 claim 在非线性下是否成立：\n\n1. **FWL invariance 是否打破？** 论文声称 Naive plug-in 对 4 种 covariate topology 产生 0% bias reduction（Section 4.5, Table 3）。这严格依赖线性投影的 column space 性质（Appendix B.2）。在 logistic regression 中 FWL 不成立——如果 matrix-based correction 在 logistic 下确实能降低 bias，这将显著改变 correction guidance。\n\n2. **ASV ranking 是否保持？** 论文未在 logistic DGP 下计算 ASV，topology vulnerability ranking 可能改变。\n\nR2 建议 \"明确 FWL 适用范围限于线性模型；logistic DGP 下验证至少一个拓扑的校正效果\"，我认为这是 reasonable 且 feasible 的要求。\n\n**建议给作者的修改优先级：SHOULD-FIX。** 至少加一个 logistic correction experiment（如 confounding + Naive plug-in）验证 FWL 是否打破。\n\n---\n\n**[AGREE with nuance] R2-N3: Conjecture 1 呈现方式不够审慎**\n\n核心关切与我的 W1 一致：ε/η 误差在极端情况下可达 1.3-1.4 δ-units，而典型 ASV 范围在 0-2，因此 \"negligible\" 一词（Section 3.3 第 99 行）确实不准确。\n\n但我要 **部分 rebut R2 的严重性判断**：\n\n1. **Conjecture 自身已有充分限定。** Conjecture 1 正文明确标注了 τ 范围和 ε 上界：front-door \"ε < 0.06 for τ ≤ 2.0; at extreme τ, normalization artifacts can increase ε to ≈0.14\"；exposure \"ε < 0.008 at the 99th percentile, though extreme-tail matrices (<0.02% of Dirichlet draws) can reach ε ≈ 0.15\"。这些不是隐藏在 appendix 中的 fine print——它们就在 Conjecture 声明中。\n\n2. **极端 ε 出现在极端参数下。** Table 8 (Appendix B.12) 显示 ε > 0.06 主要发生在 τ=0.1（mediation 0.130, confounding 0.118）和 τ=5.0（front-door 0.139）。在推荐操作范围 τ ∈ [0.5, 2.0] 内，非 IV 拓扑的 ε 均 < 0.06。\n\n3. **ε/η 的实际影响。** ε=0.06, η=0.10 时 δ* 误差 ≤ 0.6 units。在 Table 2 的 ASV 范围内（如 confounding 0.081-0.487），0.6 units 确实不 negligible——但对于 practitioner 的 binary decision（safe vs. unsafe），ASV 排名在所有测试配置中保持不变（Conjecture 1 最后一句）。\n\n**修改建议：** 将 \"negligible\" 改为 \"bounded\"，并加入一段明确讨论 ε 对 δ* 精度的定量影响。但我不认为这构成 CRITICAL 问题——Conjecture 的框架本身已足够透明。\n\n---\n\n**[AGREE] R2-W1: \"Primary coefficient never reverses\" 缺乏理论保证**\n\n与我的 W4 完全一致。论文在 Abstract 和 Section 4.4 中作为 headline finding 呈现 \"the primary treatment effect never reverses in any of 23 empirical LLM configurations\"，但这只是 23 个经验观察，不是定理。从 Eq.(2) 看，当 primary category 有 largest prevalence 且 diagonal dominance 充分时，sign reversal 确实更难发生——但论文没有 formalize 这个直觉。\n\nR2 将此标为 MINOR 合理——这是一个 framing/presentation 问题，不是方法论缺陷。\n\n---\n\n**[AGREE] R2-W2: 数字密度较高影响可读性**\n\n论文在 8 页内呈现 7 topologies × multiple metrics，数字密度确实高。但考虑到 8-page constraint 和内容的必要性，这更多是 venue limitation 而非论文缺陷。建议作者在 camera-ready 时考虑将部分数字移入 appendix，main text 只保留 key numbers。\n\n---\n\n**[AGREE] R2-W3: 符号使用存在轻微不一致（τ 在不同拓扑下含义不同）**\n\nτ 在 confounding 下是 X→Y 的因果效应，在 mediation 下是直接效应 τ_dir，在 exposure 下是 category-specific β_j，在 IV 下是 LATE。论文 Appendix C 有 notation table（Table 9），但 main text 中 τ 的含义随 topology 切换时没有明确提示。这不影响理解但增加认知负荷。\n\n---\n\n**[AGREE mildly] R2-W4: ClinicalBERT 案例研究过于简略**\n\nAppendix B.7 的案例研究用约半页篇幅做了 retrospective analysis，给出三个具体结论（sign-flip guarantee、FWL warning、correction recommendation）。作为 appendix 的定性说明，深度可以接受。但如果能加上对 ClinicalBERT confusion matrix 的定量 ASV 计算（如 \"magnitude ASV for this specific C₀ is δ*=X, indicating the study is robust/fragile\"），说服力会显著提升。\n\n---\n\n### Questions 逐条回应\n\n**[AGREE] R2-Q1: \"文本作为共同原因\" 导致的差异性误分类如何影响符号保持结论？**\n有价值的问题。如 N1 中讨论，论文应至少提供定性分析。\n\n**[AGREE] R2-Q2: DGP 参数（τ=2.0）是否代表 CSS 典型效应量？**\n重要问题。CSS 中标准化效应量通常在 [0.05, 0.5] 范围，τ=2.0（Appendix A.3 confounding DGP）偏大。Table 8 (Appendix B.12) 显示 τ=0.1 时 confounding 的 ε 升至 0.118——说明在小效应场景下，sign preservation 条件更容易违反（因为 |B_OV| 更可能 overwhelm small |τ|）。论文应明确讨论 DGP 参数选择的 representativeness，并标注 small-τ regime 的额外风险。\n\n**[AGREE] R2-Q3: 候选拓扑含 exposure 和 confounding 时如何定义 \"most conservative\" ASV？**\n有价值。论文 Limitations 说 \"compute ASV under candidate DAGs and report the most conservative\"，但没有给出操作性定义。当一种 topology 说 safe（如 confounding: sign preserved）而另一种说 dangerous（如 exposure: 83.4% sign reversal）时，\"最保守\" 意味着采用最悲观的判断，即 exposure 的结论。但这在方法论上等价于 \"DAG 不确定则假设最差情况\"，可能过于保守。建议论文至少给出一个 decision tree（类似 Algorithm 1 但加入 topology uncertainty 分支）。\n\n**[AGREE] R2-Q4: FWL 不变性在非线性模型下是否成立？**\n与 N2 重复。核心观点一致：需要实验验证。\n\n**[REBUT partially] R2-Q5: Dirichlet(1,1,1) 的 83.4% vs. 2.1%（diagonal≥0.7）的呈现**\nR2 暗示 83.4% 可能误导。但论文 **已经充分呈现了两个数字**：\n- Abstract 第 2 行：\"Under realistic LLM accuracy (diagonal ≥ 0.7), the sign reversal rate is 2.1%\"\n- Introduction Section 1 第 6 行：\"83.4% of K=3 exposure confusion matrices produce sign reversal... under realistic accuracy (diagonal ≥ 0.7), 2.1% do so\"\n- Section 4.2 第 20 行详细分层报告\n\n两个数字并列呈现，83.4% 用于建立 structural possibility（K≥3 vs K=2），2.1% 用于 practical relevance。我认为 framing 已经足够平衡。不过 R2 提出 \"informative prior matching empirical LLM distributions\" 的建议是 constructive 的——如果用拟合真实 LLM confusion matrices 的 Dirichlet(α) 做 sensitivity analysis，会更有说服力。\n\n---\n\n### Missing References 回应\n\n**[AGREE] R2-M1: Lash, Fox, Fink (2009/2021)** — quantitative bias analysis 是标注误差校正的标准参考书，论文已引用 Carroll et al. (2006) 和 Gustafson (2004) 但缺少这一本。应在 Related Work 的 measurement error 段落中补充。\n\n**[AGREE] R2-M2: Kuroki & Pearl (2014)** — measurement bias and effect restoration 与论文的 correction guidance（Section 4.5）直接相关。特别是 Kuroki & Pearl 讨论了何时可以从含测量误差的 DAG 中 restore causal effects，这与 FWL invariance 负结果形成对照。\n\n**[AGREE mildly] R2-M3: Mohan, Pearl, Tian (2013)** — 将 missing data 作为 causal problem 处理。论文已引用 Blackwell, Honaker, King (2017) 的 unified framework。Mohan et al. 提供了更基础的 graphical theory，但不是 essential gap——论文不处理 missing data，只处理 misclassification。可以在 Related Work 中以 \"related graphical approaches\" 简要提及。\n\n---\n\n### 汇总：R1 与 R2 的共识与分歧\n\n**共识点（两位 reviewer 独立提出）：**\n1. 线性 SEM / FWL invariance 的非线性 generalization 需要讨论和验证（R1-W3 ↔ R2-N2）\n2. Non-differential assumption 在 LLM 场景下需更充分讨论（R1-W2 ↔ R2-N1）\n3. Conjecture 1 的 ε 呈现需要更审慎（R1-W1 ↔ R2-N3）\n4. \"Primary coefficient never reverses\" 需要理论支撑或降级表述（R1-W4 ↔ R2-W1）\n\n**R1 独有的关切：**\n- **N1 [CRITICAL]: Theorem 1 对 K≥3 的证明不完整** — R2 未提及此问题。我仍认为这是最严重的方法论问题：一个核心 Theorem 依赖数值验证而非解析证明。\n- **N2 [CRITICAL]: Table 1 sign-flip guarantee 的条件性呈现不透明** — R2 未单独标记此问题。Table 1 的 ✓ 暗示无条件保证但实际是 DGP-conditional。\n\n**R2 独有的关切：**\n- \"文本作为共同原因\" 的具体机制分析（比我的 W2 更 specific）\n- DGP 参数 representativeness（τ=2.0 偏大）\n- ClinicalBERT 案例深度不足\n\n**Overall alignment**: 两位 reviewer 评分相同（3.5 Borderline Conference），核心关切高度重叠但侧重略不同。R1 更关注理论证明的严谨性（Theorem 1 proof gap），R2 更关注假设的实际适用性（non-differential assumption, linear SEM）。两组关切互补，共同指向论文需要在理论声明的精确性和实际适用范围的讨论上加强。",
  "reviewer_id": "1",
  "project": "causal_annot_error_attrib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "85696c1e-5ba8-4095-9b49-525c9c4bf108",
  "isSidechain": false,
  "requestId": "req_011CbHyE2w29EUs1eRViKeU8",
  "type": "assistant",
  "uuid": "36af22ea-ac9b-47ba-8046-59e11d52ca1e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W5h3RwGQiWMZQNijKXFqM6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1336,
      "cache_read_input_tokens": 98428,
      "output_tokens": 6931,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 6931,
          "cache_read_input_tokens": 98428,
          "cache_creation_input_tokens": 1336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1336
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

_source line 86_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## 交叉分享 — Reviewer 2 的完整审稿意见  请逐条回应 Reviewer 2 的每个 Weakness/Question，使用 [AGREE] 或 [REBUT] 标记，并提供具体理由（引用论文的 Section/Table/Figure 作为证据）。  ---  以下是 Reviewer 2 的完整审稿意见：  ### Overall: 3.5 (…",
  "leafUuid": "36af22ea-ac9b-47ba-8046-59e11d52ca1e",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5"
}
```

---

### Tool result

_source line 87 · 2026-05-22T17:07:01.993Z_

<details><summary>↩ Tool result · `toolu_01EAgjSwcr85LUYBT6Cpzt2j`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_9f117624057fcf6cb95db4d67f525246:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "36af22ea-ac9b-47ba-8046-59e11d52ca1e",
  "isSidechain": false,
  "promptId": "54df9cb4-68ce-4194-b5e4-49ab7f5b4caf",
  "type": "user",
  "uuid": "8182607a-aee4-4700-ae71-852ce41e0e54",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_9f117624057fcf6cb95db4d67f525246:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_9f117624057fcf6cb95db4d67f525246:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "36af22ea-ac9b-47ba-8046-59e11d52ca1e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/.claude/sessions/review_reviewer_1_210041f6",
  "sessionId": "e4d002b6-0100-4dfb-b117-a3b684ce7ac5",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

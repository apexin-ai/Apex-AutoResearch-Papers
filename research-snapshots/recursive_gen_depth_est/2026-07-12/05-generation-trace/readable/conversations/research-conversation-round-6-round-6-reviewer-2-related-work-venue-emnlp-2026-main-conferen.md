# Research conversation: [Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性） ### Venue 信息 - **目标**: EMNLP 2026 Main Conferen

**How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 82
- **Recorded user turns:** 3
- **Tool calls:** 20
- **Original source:** `logs/chats/exported-trajectories/account-1/ac6e46b8-dc91-491c-a79b-86b8c3d644fe.jsonl`
- **Structured JSON:** [`33d9e47075eceeee8e99.json`](../../sessions/33/33d9e47075eceeee8e99.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-16T19:31:09.014Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-16T19:31:09.014Z",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "content": "[Round 6 审稿请求]:\n## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）\n\n### Venue 信息\n- **目标**: EMNLP 2026 Main Conference (ARR May cycle)\n- **Deadline**: 2026-05-25\n- **格式**: ACL 模板，8 页正文 + 无限参考文献，double-blind\n- **论文路径**: projects/recursive_gen_depth_est/docs/paper/main.tex\n\n### 你的审查侧重\n新颖性定位、contribution framing、Related Work 完整性、写作质量、格式合规。\n\n### 上轮（Round 5）仍 open/in_progress 的问题\n\n请逐条检查以下问题在当前论文版本中是否已充分解决：\n\n1. **R3-N4** (in_progress): 'Universal' overclaim——应将 'universal' 全文替换为 'consistent across the three model families and strategies studied'。检查 abstract/introduction/discussion。\n2. **R1-W2** (in_progress): d0 inflation——abstract 对 transfer results 是否显式注明 d0-excluded metrics (d1-d3 balanced acc = 55.4%)？\n3. **R4-W1** (in_progress): Curation PoC non-significant (p>0.4)——是否从 contribution list 删除或降级为 'inconclusive pilot'？\n4. **R4-W3** (in_progress): 方法论新颖性有限——是否加了理论分析连接 model collapse theory？\n5. **R5-N1** (open): Perplexity tail dominance 的 novelty 受限于 Dohmatob (2024) 直接预测——Introduction/Related Work 是否明确区分了 theory prediction vs 本文贡献？\n6. **R5-W4** (open): Related Work 遗漏——Schaeffer et al. (2025) 'Model Collapse Does Not Mean What You Think'、ordinal classification 经典 Frank & Hall (2001)、Rennie & Srebro (2005)。\n7. **R3-M1** (in_progress): 引用元数据问题——he2021_deberta_v3 年份、alemohammad2024_mad 作者。\n8. **R4-W5** (in_progress): Abstract 信息密度过高（15+ 数字）。\n\n### 评审标准\n- 对每个问题��断：[RESOLVED] / [PARTIALLY ADDRESSED] / [NOT ADDRESSED] / [REGRESSED]\n- 评估论文的 novelty positioning 是否 appropriately calibrated\n- 检查 Related Work 是否遗漏重要 2024-2026 工作\n- 格式是否符合 ACL 2026 模板要求（页数、Limitations 位置、匿名性、引用格式）\n\n### 输出格式\n```\n## 遗留问题评估\n[逐条评估]\n\n## 新发现\n[如有]\n\n## Strengths（本版本）\n## Weaknesses（Must-Fix / Should-Fix / Minor）\n## Missing References\n## Questions for Authors\n## Overall Assessment\n```"
}
````

---

### Runtime record

_source line 2 · 2026-05-16T19:31:09.017Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-16T19:31:09.017Z",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

## Round 1

70 recorded events

### User

_source line 3 · 2026-05-16T19:31:09.053Z_

[Round 6 审稿请求]:
## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）

### Venue 信息
- **目标**: EMNLP 2026 Main Conference (ARR May cycle)
- **Deadline**: 2026-05-25
- **格式**: ACL 模板，8 页正文 + 无限参考文献，double-blind
- **论文路径**: projects/recursive_gen_depth_est/docs/paper/main.tex

### 你的审查侧重
新颖性定位、contribution framing、Related Work 完整性、写作质量、格式合规。

### 上轮（Round 5）仍 open/in_progress 的问题

请逐条检查以下问题在当前论文版本中是否已充分解决：

1. **R3-N4** (in_progress): 'Universal' overclaim——应将 'universal' 全文替换为 'consistent across the three model families and strategies studied'。检查 abstract/introduction/discussion。
2. **R1-W2** (in_progress): d0 inflation——abstract 对 transfer results 是否显式注明 d0-excluded metrics (d1-d3 balanced acc = 55.4%)？
3. **R4-W1** (in_progress): Curation PoC non-significant (p>0.4)——是否从 contribution list 删除或降级为 'inconclusive pilot'？
4. **R4-W3** (in_progress): 方法论新颖性有限——是否加了理论分析连接 model collapse theory？
5. **R5-N1** (open): Perplexity tail dominance 的 novelty 受限于 Dohmatob (2024) 直接预测——Introduction/Related Work 是否明确区分了 theory prediction vs 本文贡献？
6. **R5-W4** (open): Related Work 遗漏——Schaeffer et al. (2025) 'Model Collapse Does Not Mean What You Think'、ordinal classification 经典 Frank & Hall (2001)、Rennie & Srebro (2005)。
7. **R3-M1** (in_progress): 引用元数据问题——he2021_deberta_v3 年份、alemohammad2024_mad 作者。
8. **R4-W5** (in_progress): Abstract 信息密度过高（15+ 数字）。

### 评审标准
- 对每个问题��断：[RESOLVED] / [PARTIALLY ADDRESSED] / [NOT ADDRESSED] / [REGRESSED]
- 评估论文的 novelty positioning 是否 appropriately calibrated
- 检查 Related Work 是否遗漏重要 2024-2026 工作
- 格式是否符合 ACL 2026 模板要求（页数、Limitations 位置、匿名性、引用格式）

### 输出格式
```
## 遗留问题评估
[逐条评估]

## 新发现
[如有]

## Strengths（本版本）
## Weaknesses（Must-Fix / Should-Fix / Minor）
## Missing References
## Questions for Authors
## Overall Assessment
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "5aa6c39f-587a-4ac6-8802-a954ca0a585b",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-16T19:31:09.052Z_

```json
{
  "parentUuid": "5aa6c39f-587a-4ac6-8802-a954ca0a585b",
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
  "uuid": "08506643-8bee-432f-8108-c0451df1fecd",
  "timestamp": "2026-05-16T19:31:09.052Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-16T19:31:09.052Z_

```json
{
  "parentUuid": "08506643-8bee-432f-8108-c0451df1fecd",
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
  "uuid": "3dee5b77-b00b-4498-bf9d-2748f4e6c6fa",
  "timestamp": "2026-05-16T19:31:09.052Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-16T19:31:09.052Z_

```json
{
  "parentUuid": "3dee5b77-b00b-4498-bf9d-2748f4e6c6fa",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "51302f77-3c81-4de4-ad50-279ac0703d05",
  "timestamp": "2026-05-16T19:31:09.052Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
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
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Assistant

_source line 8 · 2026-05-16T19:31:14.272Z_

<details><summary>Logged reasoning block</summary>

```text
The Review Director has assigned me a Round 6 review task focusing on novelty positioning, contribution framing, Related Work completeness, writing quality, and format compliance. I need to:

1. First, search for EMNLP 2026 / ACL ARR reviewer guidelines
2. Read the paper (main.tex) to check the specific issues from Round 5
3. Evaluate each open/in_progress issue
4. Provide my assessment

Let me start by reading the paper and searching for reviewer guidelines.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "51302f77-3c81-4de4-ad50-279ac0703d05",
  "isSidechain": false,
  "requestId": "req_011Cb6oZc4eYUp8qck7p42aZ",
  "type": "assistant",
  "uuid": "ebcd747f-f1c6-40ea-92b9-972c43b95d7d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VkC7sDmbubnTXPjg1MVtvH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13867,
      "cache_read_input_tokens": 11841,
      "output_tokens": 267,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13867,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 267,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13867,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13867
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

_source line 9 · 2026-05-16T19:31:15.268Z_

我开始 Round 6 审稿，先获取 venue reviewer guidelines 和论文内容。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ebcd747f-f1c6-40ea-92b9-972c43b95d7d",
  "isSidechain": false,
  "requestId": "req_011Cb6oZc4eYUp8qck7p42aZ",
  "type": "assistant",
  "uuid": "fb62d5a0-1b8e-4927-a13c-bf225d4e3fd3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VkC7sDmbubnTXPjg1MVtvH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13867,
      "cache_read_input_tokens": 11841,
      "output_tokens": 267,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13867,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 267,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13867,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13867
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

_source line 10 · 2026-05-16T19:31:16.298Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_019udLec3831NFdsRr8q3SDx`</summary>

```json
{
  "query": "select:WebSearch,mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fb62d5a0-1b8e-4927-a13c-bf225d4e3fd3",
  "isSidechain": false,
  "requestId": "req_011Cb6oZc4eYUp8qck7p42aZ",
  "type": "assistant",
  "uuid": "d4270253-29b3-4ae6-a0e7-f76e7ca5dfdb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VkC7sDmbubnTXPjg1MVtvH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13867,
      "cache_read_input_tokens": 11841,
      "output_tokens": 267,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13867,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 267,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13867,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13867
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

_source line 11 · 2026-05-16T19:31:16.305Z_

<details><summary>↩ Tool result · `toolu_019udLec3831NFdsRr8q3SDx`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "WebSearch"
}
```

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
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d4270253-29b3-4ae6-a0e7-f76e7ca5dfdb",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "cac158e0-f80b-4aa7-bbde-0af15fd20dd3",
  "toolUseResult": {
    "matches": [
      "WebSearch",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director"
    ],
    "query": "select:WebSearch,mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "d4270253-29b3-4ae6-a0e7-f76e7ca5dfdb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 12 · 2026-05-16T19:31:22.804Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me search for the EMNLP 2026 / ACL ARR reviewer guidelines and read the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cac158e0-f80b-4aa7-bbde-0af15fd20dd3",
  "isSidechain": false,
  "requestId": "req_011Cb6oa97hFTQodFDmyy5DH",
  "type": "assistant",
  "uuid": "215328ab-7ee8-4e26-9556-3e586f086d78",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CXeoJBS732E2JmGFtFEtij",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1430,
      "cache_read_input_tokens": 25708,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1430,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 178,
          "cache_read_input_tokens": 25708,
          "cache_creation_input_tokens": 1430,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1430
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

_source line 13 · 2026-05-16T19:31:23.270Z_

<details open><summary>🔧 Tool call — WebSearch · `toolu_01DVDuJ39YRyoXS8uBVaWMqt`</summary>

```json
{
  "query": "ACL ARR 2026 reviewer guidelines review form criteria"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "215328ab-7ee8-4e26-9556-3e586f086d78",
  "isSidechain": false,
  "requestId": "req_011Cb6oa97hFTQodFDmyy5DH",
  "type": "assistant",
  "uuid": "9579516a-e9d2-4157-ab8d-684cc9dfaa62",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CXeoJBS732E2JmGFtFEtij",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1430,
      "cache_read_input_tokens": 25708,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1430,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 178,
          "cache_read_input_tokens": 25708,
          "cache_creation_input_tokens": 1430,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1430
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

_source line 14 · 2026-05-16T19:31:24.245Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CSP6KgGfbEixbWV7FjttC1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9579516a-e9d2-4157-ab8d-684cc9dfaa62",
  "isSidechain": false,
  "requestId": "req_011Cb6oa97hFTQodFDmyy5DH",
  "type": "assistant",
  "uuid": "e08ccdea-4b60-4f3c-986d-753fa4986453",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CXeoJBS732E2JmGFtFEtij",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1430,
      "cache_read_input_tokens": 25708,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1430,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 178,
          "cache_read_input_tokens": 25708,
          "cache_creation_input_tokens": 1430,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1430
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

_source line 15 · 2026-05-16T19:31:24.254Z_

<details><summary>↩ Tool result · `toolu_01CSP6KgGfbEixbWV7FjttC1`</summary>

```text
1	% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints
2	% Target: EMNLP 2026 (ARR May cycle)
3	\documentclass[11pt]{article}
4	\usepackage[review]{acl}
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage{graphicx}
8	\usepackage{booktabs}
9	\usepackage{amsmath}
10	\usepackage{amssymb}
11	\usepackage{multirow}
12	\usepackage{xcolor}
13	\usepackage{subcaption}
14	\usepackage[T1]{fontenc}
15	\usepackage[utf8]{inputenc}
16	\usepackage{microtype}
17	\usepackage{amsthm}
18	
19	\theoremstyle{definition}
20	\newtheorem{definition}{Definition}
21	
22	\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\via Statistical Fingerprints}
23	
24	\author{Anonymous}
25	
26	\begin{document}
27	\maketitle
28	
29	\input{abstract}
30	
31	\input{introduction}
32	
33	\input{related_work}
34	
35	\input{method}
36	
37	\input{atlas}
38	
39	\input{generalization}
40	
41	\input{discussion}
42	
43	\input{conclusion}
44	
45	\bibliography{references}
46	
47	\appendix
48	\input{section_appendix}
49	
50	\end{document}
51	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e08ccdea-4b60-4f3c-986d-753fa4986453",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "105ad80e-8766-4735-affc-4cbac2e69846",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex",
      "content": "% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\n% Target: EMNLP 2026 (ARR May cycle)\n\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{amsthm}\n\n\\theoremstyle{definition}\n\\newtheorem{definition}{Definition}\n\n\\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\\\via Statistical Fingerprints}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{method}\n\n\\input{atlas}\n\n\\input{generalization}\n\n\\input{discussion}\n\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{section_appendix}\n\n\\end{document}\n",
      "numLines": 51,
      "startLine": 1,
      "totalLines": 51
    }
  },
  "sourceToolAssistantUUID": "e08ccdea-4b60-4f3c-986d-753fa4986453",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-16T19:31:31.672Z_

<details><summary>↩ Tool result · `toolu_01DVDuJ39YRyoXS8uBVaWMqt`</summary>

```text
Web search results for query: "ACL ARR 2026 reviewer guidelines review form criteria"

Links: [{"title":"ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewerguidelines"},{"title":"ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/"},{"title":"ARR Area Chair Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/acguidelines"},{"title":"CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/cfp"},{"title":"Incentives 2026 – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/incentives2026"},{"title":"Review Form – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewform"},{"title":"How ARR works – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewing"},{"title":"Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/authors"},{"title":"aclrollingreview/cfp.md at main · acl-org/aclrollingreview","url":"https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"},{"title":"aclrollingreview/reviewing.md at main · acl-org/aclrollingreview","url":"https://github.com/acl-org/aclrollingreview/blob/main/reviewing.md"}]

I found the search results for ACL ARR 2026 reviewer guidelines and review form criteria. Here's what I found:

## Review Form Criteria

For Findings papers, the main criteria are soundness and reproducibility, while conference recommendations may also consider novelty, impact and other factors.

## Overall Assessment Scoring

The review form uses the following scoring scale:

- 5 = Consider for Award: The paper could be considered for an outstanding paper award at an *ACL conference (up to top 2.5% papers)
- 2 = Resubmit next cycle: The paper needs substantial revisions that can be completed by the next ARR cycle
- 1.5 = Resubmit after next cycle: The paper needs substantial revisions that cannot be completed by the next ARR cycle
- 1 = Do not resubmit: The paper has to be fully redone, or it is not relevant to the *ACL community

## Key Evaluation Areas

The review form addresses several important dimensions:

- Reproducibility: Whether there is enough information in the paper for a reader to reproduce the main results, use results in future work, or build upon this work
- Strengths: Major reasons to publish the paper at a selective *ACL venue, including novel methodology, insightful empirical results or theoretical analysis, or clear organization of related literature
- Concerns: Issues that would cause prioritizing other high-quality papers, such as correctness of results, limited impact, or lack of clarity
- Excitement: A subjective assessment of how exciting the paper is, which does not necessarily follow what is popular in the field

## Ethics Review

Reviewers must review the ACL code of ethics and the ARR checklist submitted by authors, and should describe any ethical issues and the extent to which they have been acknowledged or addressed by the authors.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9579516a-e9d2-4157-ab8d-684cc9dfaa62",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "4b6eb444-d998-4505-8650-e02cbd996b40",
  "toolUseResult": {
    "query": "ACL ARR 2026 reviewer guidelines review form criteria",
    "results": [
      {
        "tool_use_id": "srvtoolu_01Xh7ryeeaqxro2daFbro8Rs",
        "content": [
          {
            "title": "ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/reviewerguidelines"
          },
          {
            "title": "ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/"
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
            "title": "Incentives 2026 – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/incentives2026"
          },
          {
            "title": "Review Form – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/reviewform"
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
            "title": "aclrollingreview/cfp.md at main · acl-org/aclrollingreview",
            "url": "https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"
          },
          {
            "title": "aclrollingreview/reviewing.md at main · acl-org/aclrollingreview",
            "url": "https://github.com/acl-org/aclrollingreview/blob/main/reviewing.md"
          }
        ]
      },
      "I found the search results for ACL ARR 2026 reviewer guidelines and review form criteria. Here's what I found:\n\n## Review Form Criteria\n\nFor Findings papers, the main criteria are soundness and reproducibility, while conference recommendations may also consider novelty, impact and other factors.\n\n## Overall Assessment Scoring\n\nThe review form uses the following scoring scale:\n\n- 5 = Consider for Award: The paper could be considered for an outstanding paper award at an *ACL conference (up to top 2.5% papers)\n- 2 = Resubmit next cycle: The paper needs substantial revisions that can be completed by the next ARR cycle\n- 1.5 = Resubmit after next cycle: The paper needs substantial revisions that cannot be completed by the next ARR cycle\n- 1 = Do not resubmit: The paper has to be fully redone, or it is not relevant to the *ACL community\n\n## Key Evaluation Areas\n\nThe review form addresses several important dimensions:\n\n- Reproducibility: Whether there is enough information in the paper for a reader to reproduce the main results, use results in future work, or build upon this work\n- Strengths: Major reasons to publish the paper at a selective *ACL venue, including novel methodology, insightful empirical results or theoretical analysis, or clear organization of related literature\n- Concerns: Issues that would cause prioritizing other high-quality papers, such as correctness of results, limited impact, or lack of clarity\n- Excitement: A subjective assessment of how exciting the paper is, which does not necessarily follow what is popular in the field\n\n## Ethics Review\n\nReviewers must review the ACL code of ethics and the ARR checklist submitted by authors, and should describe any ethical issues and the extent to which they have been acknowledged or addressed by the authors."
    ],
    "durationSeconds": 8.397698842000002
  },
  "sourceToolAssistantUUID": "9579516a-e9d2-4157-ab8d-684cc9dfaa62",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 17_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "4b6eb444-d998-4505-8650-e02cbd996b40",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 18_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Tool call

_source line 19 · 2026-05-16T19:31:35.092Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Vkd21wiTW55qEXzPWqqFhc`</summary>

```json
{
  "query": "select:WebFetch",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4b6eb444-d998-4505-8650-e02cbd996b40",
  "isSidechain": false,
  "requestId": "req_011Cb6obGmqm7nmE2YDNo3tK",
  "type": "assistant",
  "uuid": "3da49097-d083-4aaa-9436-f073834fcbc7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DHAB4wFwKt7b1onbxB7i2a",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 478,
      "cache_creation_input_tokens": 1114,
      "cache_read_input_tokens": 27138,
      "output_tokens": 76,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1114,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 478,
          "output_tokens": 76,
          "cache_read_input_tokens": 27138,
          "cache_creation_input_tokens": 1114,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1114
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

_source line 20 · 2026-05-16T19:31:35.096Z_

<details><summary>↩ Tool result · `toolu_01Vkd21wiTW55qEXzPWqqFhc`</summary>

````text
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
  "parentUuid": "3da49097-d083-4aaa-9436-f073834fcbc7",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "8c40f64d-bb42-4e9d-8c3f-8a7e7c811536",
  "toolUseResult": {
    "matches": [
      "WebFetch"
    ],
    "query": "select:WebFetch",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "3da49097-d083-4aaa-9436-f073834fcbc7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-16T19:31:38.952Z_

<details><summary>Logged reasoning block</summary>

```text
Let me fetch the ARR review form details and read the paper sections. I need to read the individual .tex files since main.tex uses \input.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8c40f64d-bb42-4e9d-8c3f-8a7e7c811536",
  "isSidechain": false,
  "requestId": "req_011Cb6obXZ66nCEkRzjmr8Ud",
  "type": "assistant",
  "uuid": "483d40ac-576c-46d2-92f1-dae397a54abf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TogzfCfuqG585S8UjxEjTZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1072,
      "cache_read_input_tokens": 28252,
      "output_tokens": 383,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 383,
          "cache_read_input_tokens": 28252,
          "cache_creation_input_tokens": 1072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1072
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

_source line 22 · 2026-05-16T19:31:40.937Z_

<details open><summary>🔧 Tool call — WebFetch · `toolu_01AriMZZnUq3JmVvjh2TeapS`</summary>

```json
{
  "url": "https://aclrollingreview.org/reviewform",
  "prompt": "Extract the complete review form with all scoring dimensions, their scales, and descriptions. Include overall assessment scale, soundness, excitement/novelty, reproducibility, and any other rated dimensions."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "483d40ac-576c-46d2-92f1-dae397a54abf",
  "isSidechain": false,
  "requestId": "req_011Cb6obXZ66nCEkRzjmr8Ud",
  "type": "assistant",
  "uuid": "b6822696-bc84-430f-ab44-e305203920a8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TogzfCfuqG585S8UjxEjTZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1072,
      "cache_read_input_tokens": 28252,
      "output_tokens": 383,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 383,
          "cache_read_input_tokens": 28252,
          "cache_creation_input_tokens": 1072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1072
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

_source line 23 · 2026-05-16T19:31:41.468Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GJh5M3bvjHGRQRf2RpNDFX`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b6822696-bc84-430f-ab44-e305203920a8",
  "isSidechain": false,
  "requestId": "req_011Cb6obXZ66nCEkRzjmr8Ud",
  "type": "assistant",
  "uuid": "903a61a1-72ee-4421-acdb-ffd05e7503d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TogzfCfuqG585S8UjxEjTZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1072,
      "cache_read_input_tokens": 28252,
      "output_tokens": 383,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 383,
          "cache_read_input_tokens": 28252,
          "cache_creation_input_tokens": 1072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1072
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

_source line 24 · 2026-05-16T19:31:42.372Z_

<details><summary>↩ Tool result · `toolu_01GadFqZ4ZreAE5Vc9pDrSWC`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\paragraph{Model Collapse Theory.}
5	\citet{shumailov2024_nature} demonstrate that recursive training on model outputs erodes distributional tails; \citet{dohmatob2024_tale_of_tails} formalize this via scaling laws, \citet{dohmatob2025_strong_collapse} establish strong collapse guarantees, and the MAD framework \cite{alemohammad2024_mad} extends the analysis to self-consuming models.
6	Subsequent work addresses mitigation \cite{gerstgrasser2024_accumulate,drayson2025_detection_prevents_collapse,yi2026_escaping_collapse,falahati2026_curated}, non-monotonic dynamics \cite{bakshi2026_collapse_improvement}, convergence \cite{marchi2024_heat_death,wang2026_contamination}, and related phenomena \cite{knowledge_collapse2025,sigma2026_spectral,synthetic_eggs2026,dohmatob2024_demystified}.
7	These works characterize degradation but assume depth is known a priori; we address the inverse problem of estimating depth from text alone.
8	
9	\paragraph{AI Text Detection.}
10	The detection literature \cite{wu2025_detection_survey} spans statistical methods---DetectGPT \cite{mitchell2023_detectgpt}, Fast-DetectGPT \cite{fast_detectgpt2024}, Binoculars \cite{binoculars2024}, DivEye \cite{diveye2026}, GLTR \cite{gehrmann2019_gltr}, Ghostbuster \cite{verma2024_ghostbuster}, DNA-GPT \cite{yang2024_dnagpt}---and watermarking \cite{kirchenbauer2023_watermark}, with known limits from paraphrasing \cite{sadasivan2023_paraphrase}, distribution shift \cite{pudasaini2026_detection_fails}, and generator barriers \cite{pu2026_generator_barrier}.
11	M4-SemEval \cite{wang2024_m4_semeval} benchmarks multilingual detection.
12	All these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.
13	
14	\paragraph{Adjacent Tasks.}
15	EditLens \cite{editlens2026} estimates editing extent but does not model recursive chains; \citet{uchendu2020_attribution} classify \emph{which} model generated text; LOKI \cite{loki2025} benchmarks synthetic data detection across modalities.
16	\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, characterizing \emph{how} text degrades without classifying which iteration a passage comes from.
17	Our task performs the inverse---ordinal depth estimation from text alone---discriminating between adjacent depths rather than merely detecting aggregate degradation.
18	
19	\paragraph{Ordinal Classification.}
20	CORAL \cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \cite{cloc2025} extends contrastive learning with multi-margin ordinal losses.
21	We adopt both as baselines (\S\ref{sec:generalization}) to confirm the signal is accessible to principled ordinal methods.
22	
23	\paragraph{Decoding Strategy Effects.}
24	Decoding strategies shape text statistics in ways that interact with depth signals \cite{holtzman2020_nucleus,finlayson2024_closing,garces_arias2025_decoding_decoded,wiher2022_decoding,basu2021_mirostat}.
25	Our Depth Degradation Atlas (\S\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation---temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal---effects beyond single-pass text quality.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c08645c1-84b6-48eb-bfde-26baf5d8edfd",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "13b84350-1504-49f9-804c-e9ebfd9c91f6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Model Collapse Theory.}\n\\citet{shumailov2024_nature} demonstrate that recursive training on model outputs erodes distributional tails; \\citet{dohmatob2024_tale_of_tails} formalize this via scaling laws, \\citet{dohmatob2025_strong_collapse} establish strong collapse guarantees, and the MAD framework \\cite{alemohammad2024_mad} extends the analysis to self-consuming models.\nSubsequent work addresses mitigation \\cite{gerstgrasser2024_accumulate,drayson2025_detection_prevents_collapse,yi2026_escaping_collapse,falahati2026_curated}, non-monotonic dynamics \\cite{bakshi2026_collapse_improvement}, convergence \\cite{marchi2024_heat_death,wang2026_contamination}, and related phenomena \\cite{knowledge_collapse2025,sigma2026_spectral,synthetic_eggs2026,dohmatob2024_demystified}.\nThese works characterize degradation but assume depth is known a priori; we address the inverse problem of estimating depth from text alone.\n\n\\paragraph{AI Text Detection.}\nThe detection literature \\cite{wu2025_detection_survey} spans statistical methods---DetectGPT \\cite{mitchell2023_detectgpt}, Fast-DetectGPT \\cite{fast_detectgpt2024}, Binoculars \\cite{binoculars2024}, DivEye \\cite{diveye2026}, GLTR \\cite{gehrmann2019_gltr}, Ghostbuster \\cite{verma2024_ghostbuster}, DNA-GPT \\cite{yang2024_dnagpt}---and watermarking \\cite{kirchenbauer2023_watermark}, with known limits from paraphrasing \\cite{sadasivan2023_paraphrase}, distribution shift \\cite{pudasaini2026_detection_fails}, and generator barriers \\cite{pu2026_generator_barrier}.\nM4-SemEval \\cite{wang2024_m4_semeval} benchmarks multilingual detection.\nAll these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.\n\n\\paragraph{Adjacent Tasks.}\nEditLens \\cite{editlens2026} estimates editing extent but does not model recursive chains; \\citet{uchendu2020_attribution} classify \\emph{which} model generated text; LOKI \\cite{loki2025} benchmarks synthetic data detection across modalities.\n\\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, characterizing \\emph{how} text degrades without classifying which iteration a passage comes from.\nOur task performs the inverse---ordinal depth estimation from text alone---discriminating between adjacent depths rather than merely detecting aggregate degradation.\n\n\\paragraph{Ordinal Classification.}\nCORAL \\cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \\cite{cloc2025} extends contrastive learning with multi-margin ordinal losses.\nWe adopt both as baselines (\\S\\ref{sec:generalization}) to confirm the signal is accessible to principled ordinal methods.\n\n\\paragraph{Decoding Strategy Effects.}\nDecoding strategies shape text statistics in ways that interact with depth signals \\cite{holtzman2020_nucleus,finlayson2024_closing,garces_arias2025_decoding_decoded,wiher2022_decoding,basu2021_mirostat}.\nOur Depth Degradation Atlas (\\S\\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation---temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal---effects beyond single-pass text quality.",
      "numLines": 25,
      "startLine": 1,
      "totalLines": 25
    }
  },
  "sourceToolAssistantUUID": "c08645c1-84b6-48eb-bfde-26baf5d8edfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-16T19:31:41.484Z_

<details><summary>↩ Tool result · `toolu_01GJh5M3bvjHGRQRf2RpNDFX`</summary>

```text
1	\begin{abstract}
2	As large language models increasingly train on web text containing their own outputs, a recursive model$\to$data$\to$model loop arises---yet no method estimates how many such iterations a text has undergone.
3	We formalize \emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.
4	From each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics---computed against a fixed reference model.
5	A Random Forest classifier achieves 70--85\% four-class accuracy (chance = 25\%), with perplexity tail statistics emerging as consistent depth markers across all studied configurations.
6	Our \emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \emph{Effective Discriminable Depth} (EDD) metric, finding $\mathrm{EDD}_{0.75}{=}4$ for the best-characterized model family (Pythia, $p{=}0.001$; consistent direction across all three families with graded statistical support; \S4.4).
7	Cross-model transfer reaches 66.4\% (d1--d3 balanced accuracy: 55.4\%, $1.7\times$ chance); bidirectional cross-model recursive chains achieve equivalent accuracy under forward (84.75\%) and reverse (85.75\%) orderings, providing evidence for a process-level depth signal.
8	Preliminary cross-scale observations on two 7B-scale generators yield 70.2\% accuracy ($\mathrm{EDD}{=}4$) and 60.1\%; a base-model control reveals that instruction-tuning regularizes AUC decay (monotonic vs.\ non-monotonic), with weaker overall depth signal in the base variant (59.9\% vs.\ 70.2\%).
9	Applied to WikiText-103 and C4 web-crawl text, the classifiers maintain high d0 accuracy on editorial text while revealing model-dependent false positive rates on heterogeneous web content.
10	\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "903a61a1-72ee-4421-acdb-ffd05e7503d1",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "8221394d-6487-4a52-9bf1-484176f24bd2",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises---yet no method estimates how many such iterations a text has undergone.\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.\nFrom each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics---computed against a fixed reference model.\nA Random Forest classifier achieves 70--85\\% four-class accuracy (chance = 25\\%), with perplexity tail statistics emerging as consistent depth markers across all studied configurations.\nOur \\emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for the best-characterized model family (Pythia, $p{=}0.001$; consistent direction across all three families with graded statistical support; \\S4.4).\nCross-model transfer reaches 66.4\\% (d1--d3 balanced accuracy: 55.4\\%, $1.7\\times$ chance); bidirectional cross-model recursive chains achieve equivalent accuracy under forward (84.75\\%) and reverse (85.75\\%) orderings, providing evidence for a process-level depth signal.\nPreliminary cross-scale observations on two 7B-scale generators yield 70.2\\% accuracy ($\\mathrm{EDD}{=}4$) and 60.1\\%; a base-model control reveals that instruction-tuning regularizes AUC decay (monotonic vs.\\ non-monotonic), with weaker overall depth signal in the base variant (59.9\\% vs.\\ 70.2\\%).\nApplied to WikiText-103 and C4 web-crawl text, the classifiers maintain high d0 accuracy on editorial text while revealing model-dependent false positive rates on heterogeneous web content.\n\\end{abstract}",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  },
  "sourceToolAssistantUUID": "903a61a1-72ee-4421-acdb-ffd05e7503d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-16T19:31:41.886Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DS3fzE6qn6dkgMKdLPaW4R`</summary>

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
  "parentUuid": "8221394d-6487-4a52-9bf1-484176f24bd2",
  "isSidechain": false,
  "requestId": "req_011Cb6obXZ66nCEkRzjmr8Ud",
  "type": "assistant",
  "uuid": "5b64861d-1c48-4876-8e05-c6c4e080f550",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TogzfCfuqG585S8UjxEjTZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1072,
      "cache_read_input_tokens": 28252,
      "output_tokens": 383,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 383,
          "cache_read_input_tokens": 28252,
          "cache_creation_input_tokens": 1072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1072
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

_source line 27 · 2026-05-16T19:31:41.891Z_

<details><summary>↩ Tool result · `toolu_01DS3fzE6qn6dkgMKdLPaW4R`</summary>

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
12	No existing method estimates the ordinal recursive generation depth of a text passage from its content alone.
13	
14	Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \textbf{universal and scale-variant} across the three model families and three decoding strategies studied.
15	Specifically, perplexity tail statistics---the 90th-percentile perplexity (\textsc{p90\_ppl}) and surprisal variance (\textsc{var\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.
16	Surprisingly, in one of two 7B models the AUC trajectory becomes non-monotonic, suggesting that instruction tuning may alter degradation dynamics rather than scale alone driving a qualitative shift.
17	
18	We formalize recursive generation depth estimation as ordinal classification and introduce a lightweight pipeline: compute 19 reference-model perplexity features (effective dimensionality ${\approx}$4--5 due to multicollinearity; \S\ref{sec:atlas:features}) and classify with a Random Forest into $K{+}1$ depth classes.
19	To characterize how recursive generation reshapes these features, we construct the \emph{Depth Degradation Atlas}: a $3 \times 3$ grid of model families $\times$ decoding strategies spanning 4 depths (180K samples).
20	The atlas reveals strategy-dependent degradation trajectories and we introduce the \emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.
21	
22	Our contributions are:
23	\begin{itemize}
24	    \item \textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\times$ 3 decoding strategies $\times$ 4 depths.
25	
26	    \item \textbf{Depth Degradation Atlas.} A systematic $3 \times 3$ characterization reveals that perplexity tail statistics dominate depth discrimination (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and $\mathrm{EDD}_{0.75}{=}4$ for the best-characterized family (Pythia, $p{=}0.001$; consistent across all three families).
27	
28	    \item \textbf{Generalization across seven axes.} Cross-model recursive chains (84.75\%), cross-scale observations on two 7B models (70.2\% and 60.1\%), cross-domain transfer (arXiv 74.1\%), temperature robustness ($\tau \in [0.5, 0.9]$), and reference model independence ($\Delta{=}4$\,pp). A surface-text ablation (zero-shot LLMs at 30--36\%, 42\,pp below RF) confirms the signal resides in distributional statistics---while requiring only 19 features and a Random Forest for GPU-free inference.
29	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5b64861d-1c48-4876-8e05-c6c4e080f550",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "8269fbd6-629a-47d6-846c-f5f2605c1801",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive generation depth of a text passage from its content alone.\n\nOur key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \\textbf{universal and scale-variant} across the three model families and three decoding strategies studied.\nSpecifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.\nSurprisingly, in one of two 7B models the AUC trajectory becomes non-monotonic, suggesting that instruction tuning may alter degradation dynamics rather than scale alone driving a qualitative shift.\n\nWe formalize recursive generation depth estimation as ordinal classification and introduce a lightweight pipeline: compute 19 reference-model perplexity features (effective dimensionality ${\\approx}$4--5 due to multicollinearity; \\S\\ref{sec:atlas:features}) and classify with a Random Forest into $K{+}1$ depth classes.\nTo characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families $\\times$ decoding strategies spanning 4 depths (180K samples).\nThe atlas reveals strategy-dependent degradation trajectories and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\\begin{itemize}\n    \\item \\textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\\times$ 3 decoding strategies $\\times$ 4 depths.\n\n    \\item \\textbf{Depth Degradation Atlas.} A systematic $3 \\times 3$ characterization reveals that perplexity tail statistics dominate depth discrimination (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and $\\mathrm{EDD}_{0.75}{=}4$ for the best-characterized family (Pythia, $p{=}0.001$; consistent across all three families).\n\n    \\item \\textbf{Generalization across seven axes.} Cross-model recursive chains (84.75\\%), cross-scale observations on two 7B models (70.2\\% and 60.1\\%), cross-domain transfer (arXiv 74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). A surface-text ablation (zero-shot LLMs at 30--36\\%, 42\\,pp below RF) confirms the signal resides in distributional statistics---while requiring only 19 features and a Random Forest for GPU-free inference.\n\\end{itemize}",
      "numLines": 29,
      "startLine": 1,
      "totalLines": 29
    }
  },
  "sourceToolAssistantUUID": "5b64861d-1c48-4876-8e05-c6c4e080f550",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-16T19:31:42.368Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GadFqZ4ZreAE5Vc9pDrSWC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8269fbd6-629a-47d6-846c-f5f2605c1801",
  "isSidechain": false,
  "requestId": "req_011Cb6obXZ66nCEkRzjmr8Ud",
  "type": "assistant",
  "uuid": "c08645c1-84b6-48eb-bfde-26baf5d8edfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TogzfCfuqG585S8UjxEjTZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1072,
      "cache_read_input_tokens": 28252,
      "output_tokens": 383,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 383,
          "cache_read_input_tokens": 28252,
          "cache_creation_input_tokens": 1072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1072
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

_source line 29 · 2026-05-16T19:31:46.887Z_

<details><summary>↩ Tool result · `toolu_01AriMZZnUq3JmVvjh2TeapS`</summary>

```text
# ACL Rolling Review Form - Complete Scoring Dimensions

## Primary Scoring Dimensions

**Reviewer Confidence** (1-5 scale)
- 5: "Positive that my evaluation is correct. I read the paper very carefully and am familiar with related work."
- 1: "Not my area, or paper is very hard to understand."

**Soundness** (1-5 scale with half-points)
- 5: "Excellent: This study is one of the most thorough I have seen, given its type."
- 3: "Acceptable: This study provides sufficient support for its main claims."
- 1: "Major Issues: This study is not yet sufficiently thorough to warrant publication."

**Excitement** (1-5 scale with half-points)
- 5: "Highly Exciting: I would recommend this paper to others and/or attend its presentation."
- 3: "Interesting: I might mention some points of this paper to others and/or attend."
- 1: "Not Exciting: this paper does not resonate with me."

**Overall Assessment** (1-5 scale with half-points)
- 5: "Consider for Award: top 2.5% papers"
- 4: "Conference: could be accepted to an ACL conference"
- 3: "Findings: could be accepted to Findings of the ACL"
- 2: "Resubmit next cycle: needs substantial revisions"
- 1: "Do not resubmit: fully redone or irrelevant"

## Secondary Evaluation Dimensions

**Reproducibility** (1-5 scale): Reader capacity to reproduce results

**Datasets** (1-5 scale): Value of newly released datasets

**Software** (1-5 scale): Utility of released software

**Author Identity Knowledge** (1-5 scale): Reviewer's awareness of author names
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b6822696-bc84-430f-ab44-e305203920a8",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "9c15dc03-a278-4b92-b2e3-fc2fdb33527e",
  "toolUseResult": {
    "bytes": 25365,
    "code": 200,
    "codeText": "OK",
    "result": "# ACL Rolling Review Form - Complete Scoring Dimensions\n\n## Primary Scoring Dimensions\n\n**Reviewer Confidence** (1-5 scale)\n- 5: \"Positive that my evaluation is correct. I read the paper very carefully and am familiar with related work.\"\n- 1: \"Not my area, or paper is very hard to understand.\"\n\n**Soundness** (1-5 scale with half-points)\n- 5: \"Excellent: This study is one of the most thorough I have seen, given its type.\"\n- 3: \"Acceptable: This study provides sufficient support for its main claims.\"\n- 1: \"Major Issues: This study is not yet sufficiently thorough to warrant publication.\"\n\n**Excitement** (1-5 scale with half-points)\n- 5: \"Highly Exciting: I would recommend this paper to others and/or attend its presentation.\"\n- 3: \"Interesting: I might mention some points of this paper to others and/or attend.\"\n- 1: \"Not Exciting: this paper does not resonate with me.\"\n\n**Overall Assessment** (1-5 scale with half-points)\n- 5: \"Consider for Award: top 2.5% papers\"\n- 4: \"Conference: could be accepted to an ACL conference\"\n- 3: \"Findings: could be accepted to Findings of the ACL\"\n- 2: \"Resubmit next cycle: needs substantial revisions\"\n- 1: \"Do not resubmit: fully redone or irrelevant\"\n\n## Secondary Evaluation Dimensions\n\n**Reproducibility** (1-5 scale): Reader capacity to reproduce results\n\n**Datasets** (1-5 scale): Value of newly released datasets\n\n**Software** (1-5 scale): Utility of released software\n\n**Author Identity Knowledge** (1-5 scale): Reviewer's awareness of author names",
    "durationMs": 5944,
    "url": "https://aclrollingreview.org/reviewform"
  },
  "sourceToolAssistantUUID": "b6822696-bc84-430f-ab44-e305203920a8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 30_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "9c15dc03-a278-4b92-b2e3-fc2fdb33527e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 31_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Tool call

_source line 32 · 2026-05-16T19:31:50.764Z_

<details open><summary>🔧 Tool call — Read · `toolu_019MAphoeor1SSskxWvVoyCC`</summary>

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
  "parentUuid": "9c15dc03-a278-4b92-b2e3-fc2fdb33527e",
  "isSidechain": false,
  "requestId": "req_011Cb6ocPkoxAXD7iM5mSriZ",
  "type": "assistant",
  "uuid": "9ac66697-7c81-43c3-98fe-436326b90fd2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RG53E3mi59byBvKzqnqm6e",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2754,
      "cache_creation_input_tokens": 851,
      "cache_read_input_tokens": 29324,
      "output_tokens": 234,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 851,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2754,
          "output_tokens": 234,
          "cache_read_input_tokens": 29324,
          "cache_creation_input_tokens": 851,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 851
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

_source line 33 · 2026-05-16T19:31:50.768Z_

<details><summary>↩ Tool result · `toolu_019MAphoeor1SSskxWvVoyCC`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	
4	We formalized recursive generation depth estimation and showed that a compact feature set dominated by perplexity tail statistics achieves 70--85\% four-class accuracy ($\mathrm{EDD}_{0.75}{=}4$; \S\ref{sec:atlas:edd}), with five features sufficing for 97.6\% of full performance and classifier-agnostic convergence within $\leq$0.4pp.
5	The dominant feature group---perplexity tail statistics (\texttt{p90\_ppl} top-2 in 9/9 cells, \texttt{var\_surprisal} in 8/9)---generalizes across all three model families without retraining, making depth estimation a candidate early-warning signal for model collapse~\cite{shumailov2024_nature,shi2025_closer_look}; a surface-text ablation (zero-shot LLMs at 30--36\%, 42\,pp below RF; \S\ref{sec:gen:baselines}) confirms the signal resides in distributional statistics inaccessible from surface text alone.
6	Cross-strategy transfer remains the primary bottleneck (59.1\% vs.\ 66.4\% cross-model; Appendix~\ref{app:multi_tau}), confirming strategy-conditioned classifiers are necessary.
7	Depth estimation enables depth-graduated data curation---retaining d1 while filtering d3+---complementing binary detection~\cite{dsir2023,qurating2024} (Appendix~\ref{app:curation_poc}) and watermarking~\cite{kirchenbauer2023_watermark} as a provenance signal~\cite{bevendorff2025_two_paradigms}; extensions to adversarial robustness and larger generators remain open (Appendix~\ref{app:cross_scale_full}).
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9ac66697-7c81-43c3-98fe-436326b90fd2",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "7b2c8081-47e1-4fac-8cb8-c6df04fc8e13",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nWe formalized recursive generation depth estimation and showed that a compact feature set dominated by perplexity tail statistics achieves 70--85\\% four-class accuracy ($\\mathrm{EDD}_{0.75}{=}4$; \\S\\ref{sec:atlas:edd}), with five features sufficing for 97.6\\% of full performance and classifier-agnostic convergence within $\\leq$0.4pp.\nThe dominant feature group---perplexity tail statistics (\\texttt{p90\\_ppl} top-2 in 9/9 cells, \\texttt{var\\_surprisal} in 8/9)---generalizes across all three model families without retraining, making depth estimation a candidate early-warning signal for model collapse~\\cite{shumailov2024_nature,shi2025_closer_look}; a surface-text ablation (zero-shot LLMs at 30--36\\%, 42\\,pp below RF; \\S\\ref{sec:gen:baselines}) confirms the signal resides in distributional statistics inaccessible from surface text alone.\nCross-strategy transfer remains the primary bottleneck (59.1\\% vs.\\ 66.4\\% cross-model; Appendix~\\ref{app:multi_tau}), confirming strategy-conditioned classifiers are necessary.\nDepth estimation enables depth-graduated data curation---retaining d1 while filtering d3+---complementing binary detection~\\cite{dsir2023,qurating2024} (Appendix~\\ref{app:curation_poc}) and watermarking~\\cite{kirchenbauer2023_watermark} as a provenance signal~\\cite{bevendorff2025_two_paradigms}; extensions to adversarial robustness and larger generators remain open (Appendix~\\ref{app:cross_scale_full}).\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "9ac66697-7c81-43c3-98fe-436326b90fd2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-16T19:31:51.228Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BQDkdmqDLaKBKw9khCeGcw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7b2c8081-47e1-4fac-8cb8-c6df04fc8e13",
  "isSidechain": false,
  "requestId": "req_011Cb6ocPkoxAXD7iM5mSriZ",
  "type": "assistant",
  "uuid": "8e00ac92-19f3-4aba-b799-ae858cb34a69",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RG53E3mi59byBvKzqnqm6e",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2754,
      "cache_creation_input_tokens": 851,
      "cache_read_input_tokens": 29324,
      "output_tokens": 234,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 851,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2754,
          "output_tokens": 234,
          "cache_read_input_tokens": 29324,
          "cache_creation_input_tokens": 851,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 851
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

_source line 35 · 2026-05-16T19:31:51.580Z_

<details><summary>↩ Tool result · `toolu_01XqdxnF3Ude4jLkvpKzik1u`</summary>

```text
1	% ============================================================
2	% Model Collapse Theory
3	% ============================================================
4	
5	@article{shumailov2024_nature,
6	  author    = {Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},
7	  title     = {{AI models collapse when trained on recursively generated data}},
8	  journal   = {Nature},
9	  volume    = {631},
10	  pages     = {755--759},
11	  year      = {2024},
12	  doi       = {10.1038/s41586-024-07566-y},
13	}
14	
15	@inproceedings{dohmatob2024_tale_of_tails,
16	  author    = {Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, Julia},
17	  title     = {{A Tale of Tails: Model Collapse as a Change of Scaling Laws}},
18	  booktitle = {Proceedings of ICML},
19	  year      = {2024},
20	  note      = {arXiv:2402.07043},
21	  url       = {https://arxiv.org/abs/2402.07043},
22	}
23	
24	@inproceedings{dohmatob2025_strong_collapse,
25	  author    = {Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia},
26	  title     = {{Strong Model Collapse}},
27	  booktitle = {Proceedings of ICLR},
28	  year      = {2025},
29	  note      = {arXiv:2410.04840},
30	  url       = {https://arxiv.org/abs/2410.04840},
31	}
32	
33	@inproceedings{dohmatob2024_demystified,
34	  author    = {Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia},
35	  title     = {{Model Collapse Demystified: The Case of Regression}},
36	  booktitle = {Proceedings of NeurIPS},
37	  year      = {2024},
38	  note      = {arXiv:2402.07712},
39	  url       = {https://arxiv.org/abs/2402.07712},
40	}
41	
42	@inproceedings{alemohammad2024_mad,
43	  author    = {Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Hossain, Hossein and Romero, Oscar and Ramanarayanan, Sriram and Baraniuk, Richard G.},
44	  title     = {{Self-Consuming Generative Models Go MAD}},
45	  booktitle = {Proceedings of ICLR},
46	  year      = {2024},
47	  note      = {arXiv:2307.01850},
48	  url       = {https://arxiv.org/abs/2307.01850},
49	}
50	
51	@misc{gerstgrasser2024_accumulate,
52	  author    = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},
53	  title     = {{Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data}},
54	  year      = {2024},
55	  howpublished = {arXiv:2404.01413},
56	  url       = {https://arxiv.org/abs/2404.01413},
57	}
58	
59	@inproceedings{marchi2024_heat_death,
60	  author    = {Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo},
61	  title     = {{Heat Death of Generative Models in Closed-Loop Learning}},
62	  booktitle = {Proceedings of ICASSP},
63	  year      = {2024},
64	  note      = {arXiv:2404.02325},
65	  url       = {https://arxiv.org/abs/2404.02325},
66	}
67	
68	@misc{knowledge_collapse2025,
69	  author    = {Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven, Philip},
70	  title     = {{Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training}},
71	  year      = {2025},
72	  howpublished = {arXiv:2509.04796},
73	  url       = {https://arxiv.org/abs/2509.04796},
74	}
75	
76	@misc{sigma2026_spectral,
77	  author    = {Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and Priebe, Carey E. and Aue, Alexander},
78	  title     = {{SIGMA: Scalable Spectral Insights for LLM Model Collapse}},
79	  year      = {2026},
80	  howpublished = {arXiv:2601.03385},
81	  url       = {https://arxiv.org/abs/2601.03385},
82	}
83	
84	@inproceedings{mohamed2025_broken_telephone,
85	  author    = {Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan},
86	  title     = {{LLM as a Broken Telephone: Iterative Generation Distorts Information}},
87	  booktitle = {Proceedings of ACL},
88	  year      = {2025},
89	  note      = {arXiv:2502.20258},
90	  url       = {https://arxiv.org/abs/2502.20258},
91	}
92	
93	@inproceedings{synthetic_eggs2026,
94	  author    = {Schaffelder, Max and Gatt, Albert},
95	  title     = {{Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning}},
96	  booktitle = {Findings of ACL},
97	  year      = {2026},
98	  note      = {arXiv:2511.01490},
99	  url       = {https://arxiv.org/abs/2511.01490},
100	}
101	
102	@inproceedings{shi2025_closer_look,
103	  author    = {Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and Qu, Qing},
104	  title     = {{A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective}},
105	  booktitle = {Proceedings of NeurIPS},
106	  year      = {2025},
107	  note      = {Spotlight},
108	}
109	
110	@inproceedings{yi2026_escaping_collapse,
111	  author    = {Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng},
112	  title     = {{Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence}},
113	  booktitle = {3rd DATA-FM Workshop at ICLR 2026},
114	  year      = {2026},
115	}
116	
117	% --- Model collapse: collapse-can-be-avoided / contamination ---
118	
119	@inproceedings{drayson2025_detection_prevents_collapse,
120	  author    = {Drayson, George and Yilmaz, Emine and Lampos, Vasileios},
121	  title     = {{Machine-generated text detection prevents language model collapse}},
122	  booktitle = {Findings of EMNLP},
123	  year      = {2025},
124	  note      = {arXiv:2502.15654},
125	  url       = {https://arxiv.org/abs/2502.15654},
126	}
127	
128	@misc{bakshi2026_collapse_improvement,
129	  author    = {Bakshi, Soham and Chakraborty, Sunrit},
130	  title     = {{From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources}},
131	  year      = {2026},
132	  howpublished = {arXiv:2602.10531},
133	  url       = {https://arxiv.org/abs/2602.10531},
134	}
135	
136	@misc{wang2026_contamination,
137	  author    = {Wang, Kevin and Niu, Hongqian and Li, Didong},
138	  title     = {{Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training}},
139	  year      = {2026},
140	  howpublished = {arXiv:2602.16065},
141	  url       = {https://arxiv.org/abs/2602.16065},
142	}
143	
144	@misc{falahati2026_curated,
145	  author    = {Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz},
146	  title     = {{Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences}},
147	  year      = {2026},
148	  howpublished = {arXiv:2605.07724},
149	  url       = {https://arxiv.org/abs/2605.07724},
150	}
151	
152	% ============================================================
153	% AI-Generated Text Detection
154	% ============================================================
155	
156	@article{wu2025_detection_survey,
157	  author    = {Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam and Wong, Derek Fai},
158	  title     = {{A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions}},
159	  journal   = {Computational Linguistics},
160	  volume    = {51},
161	  number    = {1},
162	  pages     = {275--354},
163	  year      = {2025},
164	  publisher = {MIT Press},
165	}
166	
167	% --- Statistical / zero-shot detectors ---
168	
169	@inproceedings{gehrmann2019_gltr,
170	  author    = {Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.},
171	  title     = {{GLTR: Statistical Detection and Visualization of Generated Text}},
172	  booktitle = {Proceedings of ACL: System Demonstrations},
173	  year      = {2019},
174	  note      = {arXiv:1906.04043},
175	  url       = {https://arxiv.org/abs/1906.04043},
176	}
177	
178	@inproceedings{mitchell2023_detectgpt,
179	  author    = {Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},
180	  title     = {{DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature}},
181	  booktitle = {Proceedings of ICML},
182	  year      = {2023},
183	  note      = {arXiv:2301.11305},
184	  url       = {https://arxiv.org/abs/2301.11305},
185	}
186	
187	@inproceedings{fast_detectgpt2024,
188	  author    = {Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yue},
189	  title     = {{Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature}},
190	  booktitle = {Proceedings of ICLR},
191	  year      = {2024},
192	  note      = {arXiv:2310.05130},
193	  url       = {https://arxiv.org/abs/2310.05130},
194	}
195	
196	@inproceedings{binoculars2024,
197	  author    = {Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Hamid and Saha, Aniruddha and Goldblum, Micah and Geiping, Jonas and Goldstein, Tom},
198	  title     = {{Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text}},
199	  booktitle = {Proceedings of ICML},
200	  year      = {2024},
201	  note      = {arXiv:2401.12070},
202	  url       = {https://arxiv.org/abs/2401.12070},
203	}
204	
205	@article{diveye2026,
206	  author    = {Basani, Advik Raj and Chen, Pin-Yu},
207	  title     = {{Diversity Boosts AI-Generated Text Detection}},
208	  journal   = {Transactions on Machine Learning Research (TMLR)},
209	  year      = {2026},
210	  note      = {arXiv:2509.18880},
211	  url       = {https://arxiv.org/abs/2509.18880},
212	}
213	
214	% --- Robustness / limitations of detectors ---
215	
216	@misc{sadasivan2023_paraphrase,
217	  author    = {Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, Wenxiao and Feizi, Soheil},
218	  title     = {{Can AI-Generated Text be Reliably Detected?}},
219	  year      = {2023},
220	  howpublished = {arXiv:2303.11156},
221	  url       = {https://arxiv.org/abs/2303.11156},
222	}
223	
224	@misc{pudasaini2026_detection_fails,
225	  author    = {Pudasaini, Shushanta and Miralles-Pech{\'u}an, Luis and Lillis, David and Llorens Salvador, Marisa},
226	  title     = {{Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy}},
227	  year      = {2026},
228	  howpublished = {arXiv:2603.23146},
229	  url       = {https://arxiv.org/abs/2603.23146},
230	}
231	
232	@misc{pu2026_generator_barrier,
233	  author    = {Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli},
234	  title     = {{Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection}},
235	  year      = {2026},
236	  howpublished = {arXiv:2604.13692},
237	  url       = {https://arxiv.org/abs/2604.13692},
238	}
239	
240	% --- Beyond binary: attribution, editing extent, benchmarks ---
241	
242	@inproceedings{bevendorff2025_two_paradigms,
243	  author    = {Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin and Stein, Benno},
244	  title     = {{The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification}},
245	  booktitle = {Findings of the Association for Computational Linguistics: ACL 2025},
246	  pages     = {3762--3787},
247	  year      = {2025},
248	  address   = {Vienna, Austria},
249	}
250	
251	@inproceedings{uchendu2020_attribution,
252	  author    = {Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon},
253	  title     = {{Authorship Attribution for Neural Text Generation}},
254	  booktitle = {Proceedings of EMNLP},
255	  year      = {2020},
256	}
257	
258	@inproceedings{editlens2026,
259	  author    = {Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit},
260	  title     = {{EditLens: Quantifying the Extent of AI Editing in Text}},
261	  booktitle = {Proceedings of ICLR},
262	  year      = {2026},
263	  note      = {arXiv:2510.03154},
264	  url       = {https://arxiv.org/abs/2510.03154},
265	}
266	
267	@inproceedings{loki2025,
268	  author    = {Ye, Junyan and Zhou, Baichuan and Huang, Zilong and Zhang, Junan and Bai, Tianyi and Kang, Hengrui and He, Jun and Lin, Honglin and Wang, Zihao and Wu, Tong and Wu, Zhizheng and Chen, Yiping and Lin, Dahua and He, Conghui and Li, Weijia},
269	  title     = {{LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models}},
270	  booktitle = {Proceedings of ICLR (Spotlight)},
271	  year      = {2025},
272	  note      = {arXiv:2410.09732},
273	  url       = {https://arxiv.org/abs/2410.09732},
274	}
275	
276	% --- Statistical / feature-based / shared-task detectors ---
277	
278	@inproceedings{verma2024_ghostbuster,
279	  author    = {Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan},
280	  title     = {{Ghostbuster: Detecting Text Ghostwritten by Large Language Models}},
281	  booktitle = {Proceedings of NAACL},
282	  year      = {2024},
283	  note      = {arXiv:2305.15047},
284	  url       = {https://arxiv.org/abs/2305.15047},
285	}
286	
287	@inproceedings{wang2024_m4_semeval,
288	  author    = {Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov, Artem and Tsvigun, Akim and Afzal, Osama Mohammed and Mahmoud, Tarek and Puccetti, Giovanni and Arnold, Thomas and Whitehouse, Chenxi and Aji, Alham Fikri and Habash, Nizar and Gurevych, Iryna and Nakov, Preslav},
289	  title     = {{SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection}},
290	  booktitle = {Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2024)},
291	  year      = {2024},
292	  note      = {arXiv:2404.14183},
293	  url       = {https://arxiv.org/abs/2404.14183},
294	}
295	
296	@inproceedings{yang2024_dnagpt,
297	  author    = {Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Yang and Chen, Haifeng},
298	  title     = {{DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text}},
299	  booktitle = {Proceedings of ICLR},
300	  year      = {2024},
301	  note      = {arXiv:2305.17359},
302	  url       = {https://arxiv.org/abs/2305.17359},
303	}
304	
305	% --- Watermarking ---
306	
307	@inproceedings{kirchenbauer2023_watermark,
308	  author    = {Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Miers, Ian and Goldstein, Tom},
309	  title     = {{A Watermark for Large Language Models}},
310	  booktitle = {Proceedings of ICML},
311	  year      = {2023},
312	  note      = {arXiv:2301.10226},
313	  url       = {https://arxiv.org/abs/2301.10226},
314	}
315	
316	% ============================================================
317	% Decoding Strategies
318	% ============================================================
319	
320	@inproceedings{holtzman2020_nucleus,
321	  author    = {Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin},
322	  title     = {{The Curious Case of Neural Text Degeneration}},
323	  booktitle = {Proceedings of ICLR},
324	  year      = {2020},
325	  note      = {arXiv:1904.09751},
326	  url       = {https://arxiv.org/abs/1904.09751},
327	}
328	
329	@inproceedings{finlayson2024_closing,
330	  author    = {Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabha and Sabharwal, Ashish},
331	  title     = {{Closing the Curious Case of Neural Text Degeneration}},
332	  booktitle = {Proceedings of ICLR},
333	  year      = {2024},
334	  note      = {arXiv:2310.01693},
335	  url       = {https://arxiv.org/abs/2310.01693},
336	}
337	
338	@inproceedings{garces_arias2025_decoding_decoded,
339	  author    = {{Garces Arias}, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher, Matthias},
340	  title     = {{Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation}},
341	  booktitle = {Proceedings of COLING},
342	  year      = {2025},
343	  note      = {arXiv:2410.06097},
344	  url       = {https://arxiv.org/abs/2410.06097},
345	}
346	
347	@article{wiher2022_decoding,
348	  author    = {Wiher, Gian and Meister, Clara and Cotterell, Ryan},
349	  title     = {{On Decoding Strategies for Neural Text Generators}},
350	  journal   = {Transactions of the Association for Computational Linguistics},
351	  volume    = {10},
352	  pages     = {997--1012},
353	  year      = {2022},
354	}
355	
356	@inproceedings{basu2021_mirostat,
357	  author    = {Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shirish and Varshney, Lav R.},
358	  title     = {{Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity}},
359	  booktitle = {Proceedings of ICLR},
360	  year      = {2021},
361	}
362	
363	% ============================================================
364	% Ordinal Classification / Contrastive Learning
365	% ============================================================
366	
367	@article{coral2020,
368	  author    = {Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian},
369	  title     = {{Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation}},
370	  journal   = {Pattern Recognition Letters},
371	  volume    = {140},
372	  pages     = {325--331},
373	  year      = {2020},
374	  note      = {arXiv:1901.07884},
375	  url       = {https://arxiv.org/abs/1901.07884},
376	}
377	
378	@inproceedings{cloc2025,
379	  author    = {Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting},
380	  title     = {{CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss}},
381	  booktitle = {Proceedings of CVPR},
382	  year      = {2025},
383	  note      = {arXiv:2504.17813},
384	  url       = {https://arxiv.org/abs/2504.17813},
385	}
386	
387	% ============================================================
388	% Foundation Models / Fine-tuning
389	% ============================================================
390	
391	@inproceedings{hu2022lora,
392	  author    = {Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},
393	  title     = {{LoRA: Low-Rank Adaptation of Large Language Models}},
394	  booktitle = {Proceedings of ICLR},
395	  year      = {2022},
396	  note      = {arXiv:2106.09685},
397	  url       = {https://arxiv.org/abs/2106.09685},
398	}
399	
400	@inproceedings{he2021_deberta_v3,
401	  author    = {He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},
402	  title     = {{DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing}},
403	  booktitle = {Proceedings of ICLR},
404	  year      = {2023},
405	  note      = {arXiv:2111.09543},
406	  url       = {https://arxiv.org/abs/2111.09543},
407	}
408	
409	@article{liu2019_roberta,
410	  author    = {Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},
411	  title     = {{RoBERTa: A Robustly Optimized BERT Pretraining Approach}},
412	  journal   = {arXiv preprint arXiv:1907.11692},
413	  year      = {2019},
414	  url       = {https://arxiv.org/abs/1907.11692},
415	}
416	
417	% ============================================================
418	% Data Curation / Selection
419	% ============================================================
420	
421	@inproceedings{dsir2023,
422	  author    = {Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},
423	  title     = {{Data Selection for Language Models via Importance Resampling}},
424	  booktitle = {Proceedings of NeurIPS},
425	  year      = {2023},
426	  note      = {arXiv:2302.03169},
427	  url       = {https://arxiv.org/abs/2302.03169},
428	}
429	
430	@inproceedings{qurating2024,
431	  author    = {Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},
432	  title     = {{QuRating: Selecting High-Quality Data for Training Language Models}},
433	  booktitle = {Proceedings of ICML},
434	  year      = {2024},
435	  note      = {arXiv:2402.09739},
436	  url       = {https://arxiv.org/abs/2402.09739},
437	}
438	
439	@article{sugiyama2007_importance_weighting,
440	  author    = {Sugiyama, Masashi and Krauledat, Matthias and M{\"u}ller, Klaus-Robert},
441	  title     = {{Covariate Shift Adaptation by Importance Weighted Cross Validation}},
442	  journal   = {Journal of Machine Learning Research},
443	  volume    = {8},
444	  pages     = {985--1005},
445	  year      = {2007},
446	}
447	
448	% ============================================================
449	% Large Language Models (cross-scale experiments)
450	% ============================================================
451	
452	@misc{qwen2.5,
453	  author    = {Qwen Team},
454	  title     = {{Qwen2.5: A Party of Foundation Models}},
455	  year      = {2025},
456	  howpublished = {arXiv:2412.15115},
457	  url       = {https://arxiv.org/abs/2412.15115},
458	}
459	
460	@misc{llama3,
461	  author    = {Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav and Kadian, Abhishek and Al-Dahle, Ahmad and Letman, Aiesha and Mathur, Akhil and Schelten, Alan and others},
462	  title     = {{The Llama 3 Herd of Models}},
463	  year      = {2024},
464	  howpublished = {arXiv:2407.21783},
465	  url       = {https://arxiv.org/abs/2407.21783},
466	}
467	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "263a2278-82f2-47d8-9199-c2bccc33c7ec",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "b612899c-6b49-4f61-8b3e-670919de5bff",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib",
      "content": "% ============================================================\n% Model Collapse Theory\n% ============================================================\n\n@article{shumailov2024_nature,\n  author    = {Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},\n  title     = {{AI models collapse when trained on recursively generated data}},\n  journal   = {Nature},\n  volume    = {631},\n  pages     = {755--759},\n  year      = {2024},\n  doi       = {10.1038/s41586-024-07566-y},\n}\n\n@inproceedings{dohmatob2024_tale_of_tails,\n  author    = {Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, Julia},\n  title     = {{A Tale of Tails: Model Collapse as a Change of Scaling Laws}},\n  booktitle = {Proceedings of ICML},\n  year      = {2024},\n  note      = {arXiv:2402.07043},\n  url       = {https://arxiv.org/abs/2402.07043},\n}\n\n@inproceedings{dohmatob2025_strong_collapse,\n  author    = {Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia},\n  title     = {{Strong Model Collapse}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2025},\n  note      = {arXiv:2410.04840},\n  url       = {https://arxiv.org/abs/2410.04840},\n}\n\n@inproceedings{dohmatob2024_demystified,\n  author    = {Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia},\n  title     = {{Model Collapse Demystified: The Case of Regression}},\n  booktitle = {Proceedings of NeurIPS},\n  year      = {2024},\n  note      = {arXiv:2402.07712},\n  url       = {https://arxiv.org/abs/2402.07712},\n}\n\n@inproceedings{alemohammad2024_mad,\n  author    = {Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Hossain, Hossein and Romero, Oscar and Ramanarayanan, Sriram and Baraniuk, Richard G.},\n  title     = {{Self-Consuming Generative Models Go MAD}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2307.01850},\n  url       = {https://arxiv.org/abs/2307.01850},\n}\n\n@misc{gerstgrasser2024_accumulate,\n  author    = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},\n  title     = {{Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data}},\n  year      = {2024},\n  howpublished = {arXiv:2404.01413},\n  url       = {https://arxiv.org/abs/2404.01413},\n}\n\n@inproceedings{marchi2024_heat_death,\n  author    = {Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo},\n  title     = {{Heat Death of Generative Models in Closed-Loop Learning}},\n  booktitle = {Proceedings of ICASSP},\n  year      = {2024},\n  note      = {arXiv:2404.02325},\n  url       = {https://arxiv.org/abs/2404.02325},\n}\n\n@misc{knowledge_collapse2025,\n  author    = {Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven, Philip},\n  title     = {{Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training}},\n  year      = {2025},\n  howpublished = {arXiv:2509.04796},\n  url       = {https://arxiv.org/abs/2509.04796},\n}\n\n@misc{sigma2026_spectral,\n  author    = {Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and Priebe, Carey E. and Aue, Alexander},\n  title     = {{SIGMA: Scalable Spectral Insights for LLM Model Collapse}},\n  year      = {2026},\n  howpublished = {arXiv:2601.03385},\n  url       = {https://arxiv.org/abs/2601.03385},\n}\n\n@inproceedings{mohamed2025_broken_telephone,\n  author    = {Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan},\n  title     = {{LLM as a Broken Telephone: Iterative Generation Distorts Information}},\n  booktitle = {Proceedings of ACL},\n  year      = {2025},\n  note      = {arXiv:2502.20258},\n  url       = {https://arxiv.org/abs/2502.20258},\n}\n\n@inproceedings{synthetic_eggs2026,\n  author    = {Schaffelder, Max and Gatt, Albert},\n  title     = {{Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning}},\n  booktitle = {Findings of ACL},\n  year      = {2026},\n  note      = {arXiv:2511.01490},\n  url       = {https://arxiv.org/abs/2511.01490},\n}\n\n@inproceedings{shi2025_closer_look,\n  author    = {Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and Qu, Qing},\n  title     = {{A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective}},\n  booktitle = {Proceedings of NeurIPS},\n  year      = {2025},\n  note      = {Spotlight},\n}\n\n@inproceedings{yi2026_escaping_collapse,\n  author    = {Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng},\n  title     = {{Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence}},\n  booktitle = {3rd DATA-FM Workshop at ICLR 2026},\n  year      = {2026},\n}\n\n% --- Model collapse: collapse-can-be-avoided / contamination ---\n\n@inproceedings{drayson2025_detection_prevents_collapse,\n  author    = {Drayson, George and Yilmaz, Emine and Lampos, Vasileios},\n  title     = {{Machine-generated text detection prevents language model collapse}},\n  booktitle = {Findings of EMNLP},\n  year      = {2025},\n  note      = {arXiv:2502.15654},\n  url       = {https://arxiv.org/abs/2502.15654},\n}\n\n@misc{bakshi2026_collapse_improvement,\n  author    = {Bakshi, Soham and Chakraborty, Sunrit},\n  title     = {{From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources}},\n  year      = {2026},\n  howpublished = {arXiv:2602.10531},\n  url       = {https://arxiv.org/abs/2602.10531},\n}\n\n@misc{wang2026_contamination,\n  author    = {Wang, Kevin and Niu, Hongqian and Li, Didong},\n  title     = {{Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training}},\n  year      = {2026},\n  howpublished = {arXiv:2602.16065},\n  url       = {https://arxiv.org/abs/2602.16065},\n}\n\n@misc{falahati2026_curated,\n  author    = {Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz},\n  title     = {{Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences}},\n  year      = {2026},\n  howpublished = {arXiv:2605.07724},\n  url       = {https://arxiv.org/abs/2605.07724},\n}\n\n% ============================================================\n% AI-Generated Text Detection\n% ============================================================\n\n@article{wu2025_detection_survey,\n  author    = {Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam and Wong, Derek Fai},\n  title     = {{A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions}},\n  journal   = {Computational Linguistics},\n  volume    = {51},\n  number    = {1},\n  pages     = {275--354},\n  year      = {2025},\n  publisher = {MIT Press},\n}\n\n% --- Statistical / zero-shot detectors ---\n\n@inproceedings{gehrmann2019_gltr,\n  author    = {Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.},\n  title     = {{GLTR: Statistical Detection and Visualization of Generated Text}},\n  booktitle = {Proceedings of ACL: System Demonstrations},\n  year      = {2019},\n  note      = {arXiv:1906.04043},\n  url       = {https://arxiv.org/abs/1906.04043},\n}\n\n@inproceedings{mitchell2023_detectgpt,\n  author    = {Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},\n  title     = {{DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature}},\n  booktitle = {Proceedings of ICML},\n  year      = {2023},\n  note      = {arXiv:2301.11305},\n  url       = {https://arxiv.org/abs/2301.11305},\n}\n\n@inproceedings{fast_detectgpt2024,\n  author    = {Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yue},\n  title     = {{Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2310.05130},\n  url       = {https://arxiv.org/abs/2310.05130},\n}\n\n@inproceedings{binoculars2024,\n  author    = {Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Hamid and Saha, Aniruddha and Goldblum, Micah and Geiping, Jonas and Goldstein, Tom},\n  title     = {{Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text}},\n  booktitle = {Proceedings of ICML},\n  year      = {2024},\n  note      = {arXiv:2401.12070},\n  url       = {https://arxiv.org/abs/2401.12070},\n}\n\n@article{diveye2026,\n  author    = {Basani, Advik Raj and Chen, Pin-Yu},\n  title     = {{Diversity Boosts AI-Generated Text Detection}},\n  journal   = {Transactions on Machine Learning Research (TMLR)},\n  year      = {2026},\n  note      = {arXiv:2509.18880},\n  url       = {https://arxiv.org/abs/2509.18880},\n}\n\n% --- Robustness / limitations of detectors ---\n\n@misc{sadasivan2023_paraphrase,\n  author    = {Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, Wenxiao and Feizi, Soheil},\n  title     = {{Can AI-Generated Text be Reliably Detected?}},\n  year      = {2023},\n  howpublished = {arXiv:2303.11156},\n  url       = {https://arxiv.org/abs/2303.11156},\n}\n\n@misc{pudasaini2026_detection_fails,\n  author    = {Pudasaini, Shushanta and Miralles-Pech{\\'u}an, Luis and Lillis, David and Llorens Salvador, Marisa},\n  title     = {{Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy}},\n  year      = {2026},\n  howpublished = {arXiv:2603.23146},\n  url       = {https://arxiv.org/abs/2603.23146},\n}\n\n@misc{pu2026_generator_barrier,\n  author    = {Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli},\n  title     = {{Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection}},\n  year      = {2026},\n  howpublished = {arXiv:2604.13692},\n  url       = {https://arxiv.org/abs/2604.13692},\n}\n\n% --- Beyond binary: attribution, editing extent, benchmarks ---\n\n@inproceedings{bevendorff2025_two_paradigms,\n  author    = {Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin and Stein, Benno},\n  title     = {{The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification}},\n  booktitle = {Findings of the Association for Computational Linguistics: ACL 2025},\n  pages     = {3762--3787},\n  year      = {2025},\n  address   = {Vienna, Austria},\n}\n\n@inproceedings{uchendu2020_attribution,\n  author    = {Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon},\n  title     = {{Authorship Attribution for Neural Text Generation}},\n  booktitle = {Proceedings of EMNLP},\n  year      = {2020},\n}\n\n@inproceedings{editlens2026,\n  author    = {Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit},\n  title     = {{EditLens: Quantifying the Extent of AI Editing in Text}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2026},\n  note      = {arXiv:2510.03154},\n  url       = {https://arxiv.org/abs/2510.03154},\n}\n\n@inproceedings{loki2025,\n  author    = {Ye, Junyan and Zhou, Baichuan and Huang, Zilong and Zhang, Junan and Bai, Tianyi and Kang, Hengrui and He, Jun and Lin, Honglin and Wang, Zihao and Wu, Tong and Wu, Zhizheng and Chen, Yiping and Lin, Dahua and He, Conghui and Li, Weijia},\n  title     = {{LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models}},\n  booktitle = {Proceedings of ICLR (Spotlight)},\n  year      = {2025},\n  note      = {arXiv:2410.09732},\n  url       = {https://arxiv.org/abs/2410.09732},\n}\n\n% --- Statistical / feature-based / shared-task detectors ---\n\n@inproceedings{verma2024_ghostbuster,\n  author    = {Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan},\n  title     = {{Ghostbuster: Detecting Text Ghostwritten by Large Language Models}},\n  booktitle = {Proceedings of NAACL},\n  year      = {2024},\n  note      = {arXiv:2305.15047},\n  url       = {https://arxiv.org/abs/2305.15047},\n}\n\n@inproceedings{wang2024_m4_semeval,\n  author    = {Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov, Artem and Tsvigun, Akim and Afzal, Osama Mohammed and Mahmoud, Tarek and Puccetti, Giovanni and Arnold, Thomas and Whitehouse, Chenxi and Aji, Alham Fikri and Habash, Nizar and Gurevych, Iryna and Nakov, Preslav},\n  title     = {{SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection}},\n  booktitle = {Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2024)},\n  year      = {2024},\n  note      = {arXiv:2404.14183},\n  url       = {https://arxiv.org/abs/2404.14183},\n}\n\n@inproceedings{yang2024_dnagpt,\n  author    = {Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Yang and Chen, Haifeng},\n  title     = {{DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2305.17359},\n  url       = {https://arxiv.org/abs/2305.17359},\n}\n\n% --- Watermarking ---\n\n@inproceedings{kirchenbauer2023_watermark,\n  author    = {Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Miers, Ian and Goldstein, Tom},\n  title     = {{A Watermark for Large Language Models}},\n  booktitle = {Proceedings of ICML},\n  year      = {2023},\n  note      = {arXiv:2301.10226},\n  url       = {https://arxiv.org/abs/2301.10226},\n}\n\n% ============================================================\n% Decoding Strategies\n% ============================================================\n\n@inproceedings{holtzman2020_nucleus,\n  author    = {Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin},\n  title     = {{The Curious Case of Neural Text Degeneration}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2020},\n  note      = {arXiv:1904.09751},\n  url       = {https://arxiv.org/abs/1904.09751},\n}\n\n@inproceedings{finlayson2024_closing,\n  author    = {Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabha and Sabharwal, Ashish},\n  title     = {{Closing the Curious Case of Neural Text Degeneration}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2310.01693},\n  url       = {https://arxiv.org/abs/2310.01693},\n}\n\n@inproceedings{garces_arias2025_decoding_decoded,\n  author    = {{Garces Arias}, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher, Matthias},\n  title     = {{Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation}},\n  booktitle = {Proceedings of COLING},\n  year      = {2025},\n  note      = {arXiv:2410.06097},\n  url       = {https://arxiv.org/abs/2410.06097},\n}\n\n@article{wiher2022_decoding,\n  author    = {Wiher, Gian and Meister, Clara and Cotterell, Ryan},\n  title     = {{On Decoding Strategies for Neural Text Generators}},\n  journal   = {Transactions of the Association for Computational Linguistics},\n  volume    = {10},\n  pages     = {997--1012},\n  year      = {2022},\n}\n\n@inproceedings{basu2021_mirostat,\n  author    = {Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shirish and Varshney, Lav R.},\n  title     = {{Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2021},\n}\n\n% ============================================================\n% Ordinal Classification / Contrastive Learning\n% ============================================================\n\n@article{coral2020,\n  author    = {Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian},\n  title     = {{Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation}},\n  journal   = {Pattern Recognition Letters},\n  volume    = {140},\n  pages     = {325--331},\n  year      = {2020},\n  note      = {arXiv:1901.07884},\n  url       = {https://arxiv.org/abs/1901.07884},\n}\n\n@inproceedings{cloc2025,\n  author    = {Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting},\n  title     = {{CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss}},\n  booktitle = {Proceedings of CVPR},\n  year      = {2025},\n  note      = {arXiv:2504.17813},\n  url       = {https://arxiv.org/abs/2504.17813},\n}\n\n% ============================================================\n% Foundation Models / Fine-tuning\n% ============================================================\n\n@inproceedings{hu2022lora,\n  author    = {Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},\n  title     = {{LoRA: Low-Rank Adaptation of Large Language Models}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2022},\n  note      = {arXiv:2106.09685},\n  url       = {https://arxiv.org/abs/2106.09685},\n}\n\n@inproceedings{he2021_deberta_v3,\n  author    = {He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},\n  title     = {{DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2023},\n  note      = {arXiv:2111.09543},\n  url       = {https://arxiv.org/abs/2111.09543},\n}\n\n@article{liu2019_roberta,\n  author    = {Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},\n  title     = {{RoBERTa: A Robustly Optimized BERT Pretraining Approach}},\n  journal   = {arXiv preprint arXiv:1907.11692},\n  year      = {2019},\n  url       = {https://arxiv.org/abs/1907.11692},\n}\n\n% ============================================================\n% Data Curation / Selection\n% ============================================================\n\n@inproceedings{dsir2023,\n  author    = {Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},\n  title     = {{Data Selection for Language Models via Importance Resampling}},\n  booktitle = {Proceedings of NeurIPS},\n  year      = {2023},\n  note      = {arXiv:2302.03169},\n  url       = {https://arxiv.org/abs/2302.03169},\n}\n\n@inproceedings{qurating2024,\n  author    = {Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},\n  title     = {{QuRating: Selecting High-Quality Data for Training Language Models}},\n  booktitle = {Proceedings of ICML},\n  year      = {2024},\n  note      = {arXiv:2402.09739},\n  url       = {https://arxiv.org/abs/2402.09739},\n}\n\n@article{sugiyama2007_importance_weighting,\n  author    = {Sugiyama, Masashi and Krauledat, Matthias and M{\\\"u}ller, Klaus-Robert},\n  title     = {{Covariate Shift Adaptation by Importance Weighted Cross Validation}},\n  journal   = {Journal of Machine Learning Research},\n  volume    = {8},\n  pages     = {985--1005},\n  year      = {2007},\n}\n\n% ============================================================\n% Large Language Models (cross-scale experiments)\n% ============================================================\n\n@misc{qwen2.5,\n  author    = {Qwen Team},\n  title     = {{Qwen2.5: A Party of Foundation Models}},\n  year      = {2025},\n  howpublished = {arXiv:2412.15115},\n  url       = {https://arxiv.org/abs/2412.15115},\n}\n\n@misc{llama3,\n  author    = {Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav and Kadian, Abhishek and Al-Dahle, Ahmad and Letman, Aiesha and Mathur, Akhil and Schelten, Alan and others},\n  title     = {{The Llama 3 Herd of Models}},\n  year      = {2024},\n  howpublished = {arXiv:2407.21783},\n  url       = {https://arxiv.org/abs/2407.21783},\n}\n",
      "numLines": 467,
      "startLine": 1,
      "totalLines": 467
    }
  },
  "sourceToolAssistantUUID": "263a2278-82f2-47d8-9199-c2bccc33c7ec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-16T19:31:51.232Z_

<details><summary>↩ Tool result · `toolu_01BQDkdmqDLaKBKw9khCeGcw`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	\paragraph{Cross-strategy deployment constraint.}
5	Cross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.
6	Per-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\to}0.56$, OLMo $0.19{\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\Delta < 0.02$\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\sim}0.83$), indicating that a two-stage pipeline (strategy identification + strategy-conditioned classification) is needed for reliable cross-strategy deployment.
7	
8	\paragraph{d0 inflation of headline metrics.}
9	Depth~0 (human-written text) is near-perfectly separable (recall $>$98\% across all nine model--strategy settings), inflating headline accuracy.
10	Cross-model transfer accuracy of 66.4\% is substantially driven by d0; d2 recall drops to 26.8\% in the worst case (Pythia holdout).
11	
12	\paragraph{Controlled vs.\ ecological setting.}
13	The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\S\ref{sec:gen:crossscale}).
14	This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.
15	Depth signal is the dominant classification factor (5-fold CV 59--82\%, up to 2.5$\times$ chance): LOGO accuracy (72.1\%) matches standard CV (72.0\%), and seed-group prediction is at chance (10.2\% vs.\ 10\%; Appendix~\ref{app:domain_bias}).
16	Cross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\% vs.\ 70.2\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.
17	Real-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.
18	
19	\paragraph{Domain-dependent false positive rate.}
20	On editorial text (WikiText-103), all classifiers achieve $\geq$98.5\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL).
21	Misclassifications concentrate in template/SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\ Pythia/GPT-2~XL's Wikipedia/WebText).
22	Deployment on heterogeneous web corpora requires model- and domain-specific calibration.
23	
24	\paragraph{Adversarial robustness.}
25	Adversarial paraphrasing \cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.
26	
27	\paragraph{EDD monotonicity assumption.}
28	Our EDD definition (Eq.~\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically---as observed in all our configurations.
29	However, \citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).
30	Our cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.
31	In such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.
32	The choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.
33	
34	\paragraph{Reference model dependency.}
35	Surprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.
36	For the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.
37	Empirically, the self-model configuration does not yield the highest accuracy (Pythia 78.2\% vs.\ GPT-2~XL 85.4\%), suggesting the overlap does not confer a systematic advantage.
38	An ablation with OLMo-1B as reference model shows $\Delta$=4.0pp (\S2.3), suggesting moderate robustness; however, both reference models share similar scale (${\sim}$1B) and autoregressive architecture, so validation with architecturally distinct references (e.g., encoder-only or larger-scale models) remains open.
39	The choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.
40	
41	\paragraph{Additional caveats.}
42	Detection features degrade under domain shift \cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.
43	\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.
44	
45	\section*{Ethics Statement}
46	
47	This work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.
48	No human subjects were involved, no private or sensitive data were collected, and no new models were released.
49	Our method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.
50	Code and data will be released upon acceptance.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8e00ac92-19f3-4aba-b799-ae858cb34a69",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "7f2fc77c-08b8-4d07-93db-d532bf4d6fb5",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\n\\paragraph{Cross-strategy deployment constraint.}\nCross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.\nPer-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\\to}0.56$, OLMo $0.19{\\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\\Delta < 0.02$\\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\\sim}0.83$), indicating that a two-stage pipeline (strategy identification + strategy-conditioned classification) is needed for reliable cross-strategy deployment.\n\n\\paragraph{d0 inflation of headline metrics.}\nDepth~0 (human-written text) is near-perfectly separable (recall $>$98\\% across all nine model--strategy settings), inflating headline accuracy.\nCross-model transfer accuracy of 66.4\\% is substantially driven by d0; d2 recall drops to 26.8\\% in the worst case (Pythia holdout).\n\n\\paragraph{Controlled vs.\\ ecological setting.}\nThe primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\\S\\ref{sec:gen:crossscale}).\nThis protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.\nDepth signal is the dominant classification factor (5-fold CV 59--82\\%, up to 2.5$\\times$ chance): LOGO accuracy (72.1\\%) matches standard CV (72.0\\%), and seed-group prediction is at chance (10.2\\% vs.\\ 10\\%; Appendix~\\ref{app:domain_bias}).\nCross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\\% vs.\\ 70.2\\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.\nReal-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.\n\n\\paragraph{Domain-dependent false positive rate.}\nOn editorial text (WikiText-103), all classifiers achieve $\\geq$98.5\\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL).\nMisclassifications concentrate in template/SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\\ Pythia/GPT-2~XL's Wikipedia/WebText).\nDeployment on heterogeneous web corpora requires model- and domain-specific calibration.\n\n\\paragraph{Adversarial robustness.}\nAdversarial paraphrasing \\cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.\n\n\\paragraph{EDD monotonicity assumption.}\nOur EDD definition (Eq.~\\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically---as observed in all our configurations.\nHowever, \\citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \\emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).\nOur cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.\nIn such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.\nThe choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.\n\n\\paragraph{Reference model dependency.}\nSurprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.\nFor the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.\nEmpirically, the self-model configuration does not yield the highest accuracy (Pythia 78.2\\% vs.\\ GPT-2~XL 85.4\\%), suggesting the overlap does not confer a systematic advantage.\nAn ablation with OLMo-1B as reference model shows $\\Delta$=4.0pp (\\S2.3), suggesting moderate robustness; however, both reference models share similar scale (${\\sim}$1B) and autoregressive architecture, so validation with architecturally distinct references (e.g., encoder-only or larger-scale models) remains open.\nThe choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.\n\n\\paragraph{Additional caveats.}\nDetection features degrade under domain shift \\cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.\n\\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.\n\n\\section*{Ethics Statement}\n\nThis work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.\nNo human subjects were involved, no private or sensitive data were collected, and no new models were released.\nOur method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.\nCode and data will be released upon acceptance.",
      "numLines": 50,
      "startLine": 1,
      "totalLines": 50
    }
  },
  "sourceToolAssistantUUID": "8e00ac92-19f3-4aba-b799-ae858cb34a69",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-16T19:31:51.575Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XqdxnF3Ude4jLkvpKzik1u`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7f2fc77c-08b8-4d07-93db-d532bf4d6fb5",
  "isSidechain": false,
  "requestId": "req_011Cb6ocPkoxAXD7iM5mSriZ",
  "type": "assistant",
  "uuid": "263a2278-82f2-47d8-9199-c2bccc33c7ec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RG53E3mi59byBvKzqnqm6e",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2754,
      "cache_creation_input_tokens": 851,
      "cache_read_input_tokens": 29324,
      "output_tokens": 234,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 851,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2754,
          "output_tokens": 234,
          "cache_read_input_tokens": 29324,
          "cache_creation_input_tokens": 851,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 851
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

_source line 38 · 2026-05-16T19:31:51.635Z_

```json
{
  "parentUuid": "b612899c-6b49-4f61-8b3e-670919de5bff",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "11176684-4433-41e0-bda2-8652ef76f881",
  "timestamp": "2026-05-16T19:31:51.635Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 39_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "11176684-4433-41e0-bda2-8652ef76f881",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 40_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Assistant

_source line 41 · 2026-05-16T19:31:58.796Z_

<details><summary>Logged reasoning block</summary>

```text
Let me continue reading the references and the other sections of the paper. I need to check:
1. Whether 'universal' has been replaced
2. d0 inflation in abstract
3. Curation PoC status
4. Theory connection
5. Novelty distinction from Dohmatob (2024)
6. Missing references (Schaeffer et al., Frank & Hall, Rennie & Srebro)
7. Citation metadata issues
8. Abstract information density

Let me also read the method, atlas, and generalization sections for completeness.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "11176684-4433-41e0-bda2-8652ef76f881",
  "isSidechain": false,
  "requestId": "req_011Cb6ock5SVC6kgJjumgYj1",
  "type": "assistant",
  "uuid": "9b2b2687-255f-4f91-bc4b-1b64a2eb286e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016UiAugdXeasjXoVt74g2ty",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13608,
      "cache_read_input_tokens": 30175,
      "output_tokens": 392,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13608,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 392,
          "cache_read_input_tokens": 30175,
          "cache_creation_input_tokens": 13608,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13608
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

_source line 42 · 2026-05-16T19:32:01.156Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PNA55LV1PgbCEhbagtedYr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib",
  "offset": 467
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9b2b2687-255f-4f91-bc4b-1b64a2eb286e",
  "isSidechain": false,
  "requestId": "req_011Cb6ock5SVC6kgJjumgYj1",
  "type": "assistant",
  "uuid": "40d15be9-b5a8-471d-b16b-8b7ae51e6b77",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016UiAugdXeasjXoVt74g2ty",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13608,
      "cache_read_input_tokens": 30175,
      "output_tokens": 392,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13608,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 392,
          "cache_read_input_tokens": 30175,
          "cache_creation_input_tokens": 13608,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13608
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

_source line 43 · 2026-05-16T19:32:01.169Z_

<details><summary>↩ Tool result · `toolu_01PNA55LV1PgbCEhbagtedYr`</summary>

```text
&lt;system-reminder>Warning: the file exists but is shorter than the provided offset (467). The file has 467 lines.&lt;/system-reminder>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "40d15be9-b5a8-471d-b16b-8b7ae51e6b77",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "d92a8eb6-deac-4407-a98f-accd484f6cd4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib",
      "content": "",
      "numLines": 1,
      "startLine": 467,
      "totalLines": 467
    }
  },
  "sourceToolAssistantUUID": "40d15be9-b5a8-471d-b16b-8b7ae51e6b77",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-16T19:32:01.880Z_

<details><summary>↩ Tool result · `toolu_01Gp1XydH7aeuDSRmxw6NJAL`</summary>

```text
1	\section{The Depth Degradation Atlas}
2	\label{sec:atlas}
3	
4	We present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.
5	The atlas spans $3 \times 3 = 9$ model--strategy cells evaluated at depths $d \in \{0, 1, 2, 3\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\S\ref{sec:atlas:edd}).
6	
7	%% ----------------------------------------------------------------
8	\subsection{In-Distribution Performance}
9	\label{sec:atlas:id}
10	
11	Table~\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.
12	Accuracy ranges from 69.6\% (Pythia, top-$k$) to 85.4\% (GPT-2~XL, temperature), all exceeding the 25\% chance baseline by a wide margin.
13	Two axis effects emerge.
14	GPT-2~XL achieves the highest accuracy under every strategy (76.6--85.4\%), followed by OLMo (74.2--82.0\%) and Pythia (69.6--78.2\%).
15	Top-$k$ sampling yields the lowest accuracy in every model.
16	The mean within-model strategy gap is 8.4~pp, comparable to the 7.1~pp mean within-strategy model gap---decoding strategy and model family contribute roughly equally to performance variance.
17	
18	\begin{table}[t]
19	\centering
20	\small
21	\caption{Four-class RF accuracy (\%) across the $3 \times 3$ atlas, with d1--d3 three-class accuracy in parentheses (chance = 25\% / 33\%). Depth-0 recall exceeds 98\% in all cells.}
22	\label{tab:main_matrix}
23	\begin{tabular}{@{}lccc@{}}
24	\toprule
25	& Nucleus & Temp.\ $\tau{=}0.9$ & Top-$k$ \\
26	\midrule
27	Pythia-1.4B  & 78.2\,(71.2) & 76.3\,(70.6) & 69.6\,(58.8) \\
28	OLMo-1B     & 78.8\,(75.0) & 82.0\,(76.3) & 74.2\,(66.1) \\
29	GPT-2~XL    & 83.3\,(79.0) & 85.4\,(82.6) & 76.6\,(69.5) \\
30	\bottomrule
31	\end{tabular}
32	\end{table}
33	
34	\paragraph{Per-class recall distribution.}
35	Depth-0 recall exceeds 98\% in all 9 cells, confirming that human-written text is trivially separable from any generation depth.
36	Among generated depths, d2 consistently yields the lowest recall (46--73\% across cells), followed by d3 (58--82\%) and d1 (72--91\%).
37	For example, Pythia-1.4B nucleus achieves per-class recall of d0$\,{=}\,$99\%, d1$\,{=}\,$82\%, d2$\,{=}\,$59\%, d3$\,{=}\,$72\%.
38	The strongest d2 recall is obtained by GPT-2~XL nucleus (73\%).
39	The d2 trough reflects its position at the center of the depth gradient: d2 features overlap with both the d1 distribution above and d3 below, making it the most confusable class---consistent with the d2-vs-d3 pair being the EDD bottleneck (\S\ref{sec:atlas:edd}).
40	Full per-class recall for all cells appears in Appendix~\ref{app:per_class}.
41	
42	%% ----------------------------------------------------------------
43	\subsection{Feature Consistency Across the Grid}
44	\label{sec:atlas:features}
45	
46	Despite the 15.8~pp accuracy spread across cells, a small feature family dominates in every setting.
47	Perplexity tail statistics as a feature group dominate depth discrimination: the 90th-percentile perplexity (\texttt{p90\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\texttt{var\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\ref{app:permutation}).\footnote{Individual feature rankings should be interpreted cautiously given high multicollinearity (VIF${>}$10 for 14--16/19 features); the group-level dominance of perplexity tail statistics is robust across importance measures.}
48	Table~\ref{tab:feature_importance} shows the full per-cell ranking.
49	
50	Cross-model feature-rank Spearman correlation averages $\bar{\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.
51	Among strategies, top-$k$ yields the highest cross-model rank correlation ($\rho = 0.811$)---the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\S\ref{sec:atlas:strategy}).
52	
53	Percentile-based features outperform their moment-based counterparts.
54	Token-level perplexity distributions are heavy-tailed: individual outlier passages can dominate the arithmetic mean of their depth class, whereas \texttt{p90\_ppl} is robust to such extremes while still capturing the tail erosion that signals generation depth.
55	
56	Feature ablation confirms this concentration: the top-2 features (\texttt{p90\_ppl} + \texttt{var\_surprisal}) alone reach 91.1\% of full accuracy (71.5\%), and the top-5 features achieve 97.6\% (76.5\% vs.\ 78.4\%), with perplexity statistics alone reaching 76.6\% (vs.\ surprisal 73.2\%, other categories ${\leq}$47\%).
57	Variance inflation analysis reveals VIF${>}$10 for 14--16 of 19 features, placing the effective independent dimensionality at ${\approx}$4--5.
58	Forward selection independently confirms the dominant pair: \texttt{p90\_ppl} is selected first in 6/9 cells, \texttt{var\_surprisal} in 3/9.
59	
60	The feature hierarchy also shifts with depth.
61	At shallow boundaries (d1 vs.\ d2), \texttt{var\_surprisal} dominates importance; at deeper boundaries (d3 vs.\ d4, d4 vs.\ d5), tail perplexity statistics (\texttt{p90\_ppl}, \texttt{kurtosis\_ppl}) take over.
62	This transition aligns with model-collapse dynamics~\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).
63	
64	\begin{table}[t]
65	\centering
66	\small
67	\caption{Top-5 features by Gini importance. \textbf{Bold}: top-2. \texttt{p90\_ppl} top-2 in 9/9; \texttt{var\_surprisal} 8/9 under SHAP (7/9 under Gini).}
68	\label{tab:feature_importance}
69	\resizebox{\columnwidth}{!}{%
70	\begin{tabular}{@{}l l@{}}
71	\toprule
72	Cell & Top-5 features (Gini importance, ranked) \\
73	\midrule
74	Pythia, nuc.       & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.15)}, m\_ppl\,(.11), var\_ppl\,(.08), p75\,(.07) \\
75	Pythia, $\tau$     & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.14)}, m\_ppl\,(.11), p75\,(.07), m\_surp\,(.07) \\
76	Pythia, top-$k$    & \textbf{var\_surp\,(.16)}, \textbf{p90\_ppl\,(.12)}, m\_ppl\,(.11), var\_ppl\,(.07), m\_surp\,(.06) \\
77	GPT-2\,XL, nuc.    & \textbf{var\_surp\,(.21)}, \textbf{p90\_ppl\,(.21)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.06) \\
78	GPT-2\,XL, $\tau$  & \textbf{p90\_ppl\,(.25)}, \textbf{p75\,(.15)}, m\_surp\,(.13), var\_surp\,(.12), p50\,(.05) \\
79	GPT-2\,XL, top-$k$ & \textbf{p90\_ppl\,(.24)}, \textbf{p75\,(.12)}, var\_surp\,(.10), m\_surp\,(.09), ttr\,(.04) \\
80	OLMo, nuc.         & \textbf{p90\_ppl\,(.18)}, \textbf{var\_surp\,(.15)}, p75\,(.11), m\_surp\,(.07), ttr\,(.06) \\
81	OLMo, $\tau$       & \textbf{p90\_ppl\,(.21)}, \textbf{var\_surp\,(.16)}, p75\,(.12), m\_surp\,(.09), ttr\,(.05) \\
82	OLMo, top-$k$      & \textbf{p90\_ppl\,(.20)}, \textbf{var\_surp\,(.17)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.05) \\
83	\bottomrule
84	\end{tabular}}
85	\end{table}
86	
87	\begin{figure}[t]
88	\centering
89	\includegraphics[width=\columnwidth]{figures/fig_atlas_heatmap.pdf}
90	\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\S\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}
91	\label{fig:atlas_heatmap}
92	\end{figure}
93	
94	%% ----------------------------------------------------------------
95	\subsection{Monotonicity and Inter-Depth Distances}
96	\label{sec:atlas:monotonicity}
97	
98	Depth features exhibit strong monotonic trends: perplexity tail statistics (\texttt{p90\_ppl}, \texttt{mean\_surprisal}) decrease with depth (Spearman $\rho = -1.0$ across cell-level medians) while repetition features increase, reflecting the complementary narrowing and self-repetition of distribution collapse.
99	Inter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89---separating adjacent deep generations requires the tail statistics identified in \S\ref{sec:atlas:features}.
100	
101	\begin{figure}[t]
102	\centering
103	\includegraphics[width=\columnwidth]{figures/fig_feature_trajectory.pdf}
104	\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \texttt{p90\_ppl} (monotonically decreasing). Middle: \texttt{var\_surprisal} (decreasing). Bottom: \texttt{rep\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \to d{=}1$ gap exceeds all subsequent inter-depth gaps.}
105	\label{fig:feature_trajectory}
106	\end{figure}
107	
108	%% ----------------------------------------------------------------
109	\subsection{EDD Analysis}
110	\label{sec:atlas:edd}
111	
112	We extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.
113	Each model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).
114	We train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\ref{eq:edd}.
115	
116	\paragraph{AUC decay profile.}
117	Figure~\ref{fig:auc_decay} plots the binary pairwise AUC decay curves.
118	For Pythia-1.4B (nucleus), AUC decays monotonically: d0-vs-d1 $= 0.999$, d1-vs-d2 $= 0.925$, d2-vs-d3 $= 0.823$, d3-vs-d4 $= 0.784$, d4-vs-d5 $= 0.683$.
119	The steepest drop occurs between the d1-vs-d2 and d2-vs-d3 pairs; the curve then flattens as the system approaches an indistinguishable regime gradually rather than crossing a sharp boundary.
120	
121	\paragraph{Cross-model convergence at depth 4--5.}
122	The d3-vs-d4 AUC consistently clusters near the $T{=}0.75$ threshold across all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$ ($0.681$--$0.684$).
123	The directional pattern is consistent, but statistical strength is stratified: bootstrap testing ($10{,}000$ resamples, $H_0{:}\, \mathrm{AUC} \leq 0.75$) yields $p = 0.001$ for Pythia (significant), $p = 0.091$ for OLMo (marginal), and $p = 0.505$ for GPT-2~XL (non-significant).
124	All three models cross the $T{=}0.75$ threshold within the d3--d4 region, establishing a consistent depth-4 decay boundary with graded confidence rather than uniform statistical significance.
125	The d4-vs-d5 saturation is unambiguous across models, supporting the interpretation of d3--d4 as a \emph{transition zone} from discriminable to indistinguishable regime.
126	
127	\paragraph{EDD threshold sensitivity.}
128	Table~\ref{tab:edd_sensitivity} reports $\mathrm{EDD}_T$ across the primary 9-cell benchmark (depths 0--3) at four threshold values.
129	At $T{=}0.65$, all 9 cells achieve $\mathrm{EDD} = 3$; at $T{=}0.75$, 7 of 9 cells maintain $\mathrm{EDD} \geq 3$; at $T{=}0.80$, the count drops to 5 of 9.
130	The cells losing $\mathrm{EDD}{=}3$ first are consistently the top-$k$ configurations (Pythia top-$k$ at $T{=}0.70$, then OLMo top-$k$ at $T{=}0.75$), where the d2-vs-d3 pair is the consistent bottleneck across all 9 cells.
131	
132	\begin{table}[t]
133	\centering
134	\small
135	\caption{Number of atlas cells achieving $\mathrm{EDD} \geq 3$ at each threshold $T$, across 9 model--strategy cells (depths 0--3). The d2-vs-d3 boundary is the bottleneck; top-$k$ cells drop first.}
136	\label{tab:edd_sensitivity}
137	\begin{tabular}{@{}lcccc@{}}
138	\toprule
139	& $T{=}0.65$ & $T{=}0.70$ & $T{=}0.75$ & $T{=}0.80$ \\
140	\midrule
141	Cells with $\mathrm{EDD} \geq 3$ & 9/9 & 8/9 & 7/9 & 5/9 \\
142	\bottomrule
143	\end{tabular}
144	\end{table}
145	
146	\begin{figure}[t]
147	\centering
148	\includegraphics[width=\columnwidth]{figures/fig_auc_decay.pdf}
149	\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \in \{0.65, 0.70, 0.75, 0.80\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\% CIs.}
150	\label{fig:auc_decay}
151	\end{figure}
152	
153	\paragraph{Decision boundary dilution.}
154	\label{sec:atlas:edd:dilution}
155	EDD uses binary-pair classifiers to avoid \emph{decision boundary dilution}: in Pythia nucleus, d2\,vs.\,d3 AUC degrades from 0.804 (4-class) to 0.689 (6-class)---a 14.3\% relative decline despite identical data---because shared decision boundaries dilute per-pair capacity.
156	Binary classifiers eliminate this confound, isolating true adjacent-pair discriminability.
157	
158	%% ----------------------------------------------------------------
159	\subsection{Strategy-Dependent Trajectories}
160	\label{sec:atlas:strategy}
161	
162	The three decoding strategies induce qualitatively distinct degradation trajectories.
163	Nucleus ($p{=}0.95$) produces the most consistent accuracy (78.2--83.3\%) and serves as the reference trajectory.
164	Temperature ($\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.4\%, OLMo 82.0\%) because uniform logit scaling accelerates convergence to an attractor distribution~\cite{shumailov2024_nature}, amplifying the statistical fingerprint---but this acceleration creates a boundary reversal risk: temperature depth-$N$ features approximate nucleus/top-$k$ depth-$(N{+}1)$ features, causing cross-strategy classifiers to systematically overpredict depth (\S\ref{sec:generalization}).
165	Top-$k$ ($k{=}50$) produces the lowest accuracy (69.6--76.6\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens, though feature direction is preserved (cross-model $\rho = 0.811$).
166	The strategy effect (8.4~pp range) exceeds the model effect (7.1~pp), indicating deployment-time knowledge of the decoding strategy matters at least as much as the generator model.
167	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bc0f0076-42bb-4c5c-8d0b-3f8d2095cc86",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "5c7c35d8-d8a0-4ed5-b1bb-0205b7b74e4b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "content": "\\section{The Depth Degradation Atlas}\n\\label{sec:atlas}\n\nWe present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.\nThe atlas spans $3 \\times 3 = 9$ model--strategy cells evaluated at depths $d \\in \\{0, 1, 2, 3\\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\\S\\ref{sec:atlas:edd}).\n\n%% ----------------------------------------------------------------\n\\subsection{In-Distribution Performance}\n\\label{sec:atlas:id}\n\nTable~\\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.\nAccuracy ranges from 69.6\\% (Pythia, top-$k$) to 85.4\\% (GPT-2~XL, temperature), all exceeding the 25\\% chance baseline by a wide margin.\nTwo axis effects emerge.\nGPT-2~XL achieves the highest accuracy under every strategy (76.6--85.4\\%), followed by OLMo (74.2--82.0\\%) and Pythia (69.6--78.2\\%).\nTop-$k$ sampling yields the lowest accuracy in every model.\nThe mean within-model strategy gap is 8.4~pp, comparable to the 7.1~pp mean within-strategy model gap---decoding strategy and model family contribute roughly equally to performance variance.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Four-class RF accuracy (\\%) across the $3 \\times 3$ atlas, with d1--d3 three-class accuracy in parentheses (chance = 25\\% / 33\\%). Depth-0 recall exceeds 98\\% in all cells.}\n\\label{tab:main_matrix}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n& Nucleus & Temp.\\ $\\tau{=}0.9$ & Top-$k$ \\\\\n\\midrule\nPythia-1.4B  & 78.2\\,(71.2) & 76.3\\,(70.6) & 69.6\\,(58.8) \\\\\nOLMo-1B     & 78.8\\,(75.0) & 82.0\\,(76.3) & 74.2\\,(66.1) \\\\\nGPT-2~XL    & 83.3\\,(79.0) & 85.4\\,(82.6) & 76.6\\,(69.5) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Per-class recall distribution.}\nDepth-0 recall exceeds 98\\% in all 9 cells, confirming that human-written text is trivially separable from any generation depth.\nAmong generated depths, d2 consistently yields the lowest recall (46--73\\% across cells), followed by d3 (58--82\\%) and d1 (72--91\\%).\nFor example, Pythia-1.4B nucleus achieves per-class recall of d0$\\,{=}\\,$99\\%, d1$\\,{=}\\,$82\\%, d2$\\,{=}\\,$59\\%, d3$\\,{=}\\,$72\\%.\nThe strongest d2 recall is obtained by GPT-2~XL nucleus (73\\%).\nThe d2 trough reflects its position at the center of the depth gradient: d2 features overlap with both the d1 distribution above and d3 below, making it the most confusable class---consistent with the d2-vs-d3 pair being the EDD bottleneck (\\S\\ref{sec:atlas:edd}).\nFull per-class recall for all cells appears in Appendix~\\ref{app:per_class}.\n\n%% ----------------------------------------------------------------\n\\subsection{Feature Consistency Across the Grid}\n\\label{sec:atlas:features}\n\nDespite the 15.8~pp accuracy spread across cells, a small feature family dominates in every setting.\nPerplexity tail statistics as a feature group dominate depth discrimination: the 90th-percentile perplexity (\\texttt{p90\\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\\texttt{var\\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\\ref{app:permutation}).\\footnote{Individual feature rankings should be interpreted cautiously given high multicollinearity (VIF${>}$10 for 14--16/19 features); the group-level dominance of perplexity tail statistics is robust across importance measures.}\nTable~\\ref{tab:feature_importance} shows the full per-cell ranking.\n\nCross-model feature-rank Spearman correlation averages $\\bar{\\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.\nAmong strategies, top-$k$ yields the highest cross-model rank correlation ($\\rho = 0.811$)---the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\\S\\ref{sec:atlas:strategy}).\n\nPercentile-based features outperform their moment-based counterparts.\nToken-level perplexity distributions are heavy-tailed: individual outlier passages can dominate the arithmetic mean of their depth class, whereas \\texttt{p90\\_ppl} is robust to such extremes while still capturing the tail erosion that signals generation depth.\n\nFeature ablation confirms this concentration: the top-2 features (\\texttt{p90\\_ppl} + \\texttt{var\\_surprisal}) alone reach 91.1\\% of full accuracy (71.5\\%), and the top-5 features achieve 97.6\\% (76.5\\% vs.\\ 78.4\\%), with perplexity statistics alone reaching 76.6\\% (vs.\\ surprisal 73.2\\%, other categories ${\\leq}$47\\%).\nVariance inflation analysis reveals VIF${>}$10 for 14--16 of 19 features, placing the effective independent dimensionality at ${\\approx}$4--5.\nForward selection independently confirms the dominant pair: \\texttt{p90\\_ppl} is selected first in 6/9 cells, \\texttt{var\\_surprisal} in 3/9.\n\nThe feature hierarchy also shifts with depth.\nAt shallow boundaries (d1 vs.\\ d2), \\texttt{var\\_surprisal} dominates importance; at deeper boundaries (d3 vs.\\ d4, d4 vs.\\ d5), tail perplexity statistics (\\texttt{p90\\_ppl}, \\texttt{kurtosis\\_ppl}) take over.\nThis transition aligns with model-collapse dynamics~\\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Top-5 features by Gini importance. \\textbf{Bold}: top-2. \\texttt{p90\\_ppl} top-2 in 9/9; \\texttt{var\\_surprisal} 8/9 under SHAP (7/9 under Gini).}\n\\label{tab:feature_importance}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}l l@{}}\n\\toprule\nCell & Top-5 features (Gini importance, ranked) \\\\\n\\midrule\nPythia, nuc.       & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.15)}, m\\_ppl\\,(.11), var\\_ppl\\,(.08), p75\\,(.07) \\\\\nPythia, $\\tau$     & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.14)}, m\\_ppl\\,(.11), p75\\,(.07), m\\_surp\\,(.07) \\\\\nPythia, top-$k$    & \\textbf{var\\_surp\\,(.16)}, \\textbf{p90\\_ppl\\,(.12)}, m\\_ppl\\,(.11), var\\_ppl\\,(.07), m\\_surp\\,(.06) \\\\\nGPT-2\\,XL, nuc.    & \\textbf{var\\_surp\\,(.21)}, \\textbf{p90\\_ppl\\,(.21)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.06) \\\\\nGPT-2\\,XL, $\\tau$  & \\textbf{p90\\_ppl\\,(.25)}, \\textbf{p75\\,(.15)}, m\\_surp\\,(.13), var\\_surp\\,(.12), p50\\,(.05) \\\\\nGPT-2\\,XL, top-$k$ & \\textbf{p90\\_ppl\\,(.24)}, \\textbf{p75\\,(.12)}, var\\_surp\\,(.10), m\\_surp\\,(.09), ttr\\,(.04) \\\\\nOLMo, nuc.         & \\textbf{p90\\_ppl\\,(.18)}, \\textbf{var\\_surp\\,(.15)}, p75\\,(.11), m\\_surp\\,(.07), ttr\\,(.06) \\\\\nOLMo, $\\tau$       & \\textbf{p90\\_ppl\\,(.21)}, \\textbf{var\\_surp\\,(.16)}, p75\\,(.12), m\\_surp\\,(.09), ttr\\,(.05) \\\\\nOLMo, top-$k$      & \\textbf{p90\\_ppl\\,(.20)}, \\textbf{var\\_surp\\,(.17)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.05) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_atlas_heatmap.pdf}\n\\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\\S\\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}\n\\label{fig:atlas_heatmap}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{Monotonicity and Inter-Depth Distances}\n\\label{sec:atlas:monotonicity}\n\nDepth features exhibit strong monotonic trends: perplexity tail statistics (\\texttt{p90\\_ppl}, \\texttt{mean\\_surprisal}) decrease with depth (Spearman $\\rho = -1.0$ across cell-level medians) while repetition features increase, reflecting the complementary narrowing and self-repetition of distribution collapse.\nInter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89---separating adjacent deep generations requires the tail statistics identified in \\S\\ref{sec:atlas:features}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_feature_trajectory.pdf}\n\\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \\texttt{p90\\_ppl} (monotonically decreasing). Middle: \\texttt{var\\_surprisal} (decreasing). Bottom: \\texttt{rep\\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \\to d{=}1$ gap exceeds all subsequent inter-depth gaps.}\n\\label{fig:feature_trajectory}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{EDD Analysis}\n\\label{sec:atlas:edd}\n\nWe extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.\nEach model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).\nWe train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\\ref{eq:edd}.\n\n\\paragraph{AUC decay profile.}\nFigure~\\ref{fig:auc_decay} plots the binary pairwise AUC decay curves.\nFor Pythia-1.4B (nucleus), AUC decays monotonically: d0-vs-d1 $= 0.999$, d1-vs-d2 $= 0.925$, d2-vs-d3 $= 0.823$, d3-vs-d4 $= 0.784$, d4-vs-d5 $= 0.683$.\nThe steepest drop occurs between the d1-vs-d2 and d2-vs-d3 pairs; the curve then flattens as the system approaches an indistinguishable regime gradually rather than crossing a sharp boundary.\n\n\\paragraph{Cross-model convergence at depth 4--5.}\nThe d3-vs-d4 AUC consistently clusters near the $T{=}0.75$ threshold across all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$ ($0.681$--$0.684$).\nThe directional pattern is consistent, but statistical strength is stratified: bootstrap testing ($10{,}000$ resamples, $H_0{:}\\, \\mathrm{AUC} \\leq 0.75$) yields $p = 0.001$ for Pythia (significant), $p = 0.091$ for OLMo (marginal), and $p = 0.505$ for GPT-2~XL (non-significant).\nAll three models cross the $T{=}0.75$ threshold within the d3--d4 region, establishing a consistent depth-4 decay boundary with graded confidence rather than uniform statistical significance.\nThe d4-vs-d5 saturation is unambiguous across models, supporting the interpretation of d3--d4 as a \\emph{transition zone} from discriminable to indistinguishable regime.\n\n\\paragraph{EDD threshold sensitivity.}\nTable~\\ref{tab:edd_sensitivity} reports $\\mathrm{EDD}_T$ across the primary 9-cell benchmark (depths 0--3) at four threshold values.\nAt $T{=}0.65$, all 9 cells achieve $\\mathrm{EDD} = 3$; at $T{=}0.75$, 7 of 9 cells maintain $\\mathrm{EDD} \\geq 3$; at $T{=}0.80$, the count drops to 5 of 9.\nThe cells losing $\\mathrm{EDD}{=}3$ first are consistently the top-$k$ configurations (Pythia top-$k$ at $T{=}0.70$, then OLMo top-$k$ at $T{=}0.75$), where the d2-vs-d3 pair is the consistent bottleneck across all 9 cells.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Number of atlas cells achieving $\\mathrm{EDD} \\geq 3$ at each threshold $T$, across 9 model--strategy cells (depths 0--3). The d2-vs-d3 boundary is the bottleneck; top-$k$ cells drop first.}\n\\label{tab:edd_sensitivity}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n& $T{=}0.65$ & $T{=}0.70$ & $T{=}0.75$ & $T{=}0.80$ \\\\\n\\midrule\nCells with $\\mathrm{EDD} \\geq 3$ & 9/9 & 8/9 & 7/9 & 5/9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_auc_decay.pdf}\n\\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\\% CIs.}\n\\label{fig:auc_decay}\n\\end{figure}\n\n\\paragraph{Decision boundary dilution.}\n\\label{sec:atlas:edd:dilution}\nEDD uses binary-pair classifiers to avoid \\emph{decision boundary dilution}: in Pythia nucleus, d2\\,vs.\\,d3 AUC degrades from 0.804 (4-class) to 0.689 (6-class)---a 14.3\\% relative decline despite identical data---because shared decision boundaries dilute per-pair capacity.\nBinary classifiers eliminate this confound, isolating true adjacent-pair discriminability.\n\n%% ----------------------------------------------------------------\n\\subsection{Strategy-Dependent Trajectories}\n\\label{sec:atlas:strategy}\n\nThe three decoding strategies induce qualitatively distinct degradation trajectories.\nNucleus ($p{=}0.95$) produces the most consistent accuracy (78.2--83.3\\%) and serves as the reference trajectory.\nTemperature ($\\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.4\\%, OLMo 82.0\\%) because uniform logit scaling accelerates convergence to an attractor distribution~\\cite{shumailov2024_nature}, amplifying the statistical fingerprint---but this acceleration creates a boundary reversal risk: temperature depth-$N$ features approximate nucleus/top-$k$ depth-$(N{+}1)$ features, causing cross-strategy classifiers to systematically overpredict depth (\\S\\ref{sec:generalization}).\nTop-$k$ ($k{=}50$) produces the lowest accuracy (69.6--76.6\\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens, though feature direction is preserved (cross-model $\\rho = 0.811$).\nThe strategy effect (8.4~pp range) exceeds the model effect (7.1~pp), indicating deployment-time knowledge of the decoding strategy matters at least as much as the generator model.\n",
      "numLines": 167,
      "startLine": 1,
      "totalLines": 167
    }
  },
  "sourceToolAssistantUUID": "bc0f0076-42bb-4c5c-8d0b-3f8d2095cc86",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-16T19:32:01.670Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WuqX9XQJ9EEszcfBB9QFzf`</summary>

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
  "parentUuid": "d92a8eb6-deac-4407-a98f-accd484f6cd4",
  "isSidechain": false,
  "requestId": "req_011Cb6ock5SVC6kgJjumgYj1",
  "type": "assistant",
  "uuid": "79ac53c9-163d-40a1-b402-1360acec471c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016UiAugdXeasjXoVt74g2ty",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13608,
      "cache_read_input_tokens": 30175,
      "output_tokens": 392,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13608,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 392,
          "cache_read_input_tokens": 30175,
          "cache_creation_input_tokens": 13608,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13608
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

_source line 46 · 2026-05-16T19:32:01.681Z_

<details><summary>↩ Tool result · `toolu_01WuqX9XQJ9EEszcfBB9QFzf`</summary>

```text
1	\section{Method}
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
26	Our findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.
27	
28	\paragraph{Depth and scale.}
29	The primary benchmark covers depths d0--d3 across all $3 \times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).
30	For depth extension experiments (\S\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.
31	
32	\paragraph{Generation pipeline.}
33	Starting from a Wikipedia subset as seed text ($\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \cite{hu2022lora} on $\mathcal{D}_{k-1}$, freezing base model weights and training low-rank update matrices ($<$1\% additional parameters; $r{=}16$, $\alpha{=}32$, lr $2{\times}10^{-4}$, batch size 8, 3 epochs, dropout $0.05$, architecture-specific targets); (2)~sampling 5{,}000 passages from the LoRA-finetuned model (max 512 tokens, BOS-seeded, no prompt conditioning) under the specified decoding strategy; (3)~the generated corpus becomes $\mathcal{D}_k$ for the next cycle.
34	Each depth is produced by a model explicitly trained on the prior depth's data---not by sampling from the unmodified base model.
35	Our BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work.
36	There is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.
37	
38	\paragraph{Reference model.}
39	All statistical features (\S\ref{sec:method:features}) are computed using Pythia-1.4B as fixed reference model, the smallest generator whose training corpus partially overlaps with the others.
40	For Pythia this constitutes self-model measurement, yet its accuracy (78.2\%) does not exceed GPT-2~XL (85.4\%), indicating no systematic self-model advantage.
41	An ablation with OLMo-1B as reference yields $\Delta$=4.0pp (Appendix~\ref{tab:ref_ablation}); further discussion in Limitations.
42	
43	\subsection{Statistical Feature Design}
44	\label{sec:method:features}
45	
46	We extract a feature vector $\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\S\ref{sec:atlas:features}) shows the top 5 achieve 97.6\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features, placing the effective independent dimensionality at ${\approx}$4--5.
47	The features fall into four categories (Table~\ref{tab:features}).
48	
49	\begin{table}[t]
50	\centering
51	\small
52	\caption{The 19 statistical features comprising $\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}
53	\label{tab:features}
54	\begin{tabular}{@{}llr@{}}
55	\toprule
56	Category & Features & $n$ \\
57	\midrule
58	Perplexity & mean, var, skewness, kurtosis, & 9 \\
59	statistics & p10, p25, p50, p75, p90 & \\
60	\addlinespace
61	Surprisal & mean, var, entropy & 3 \\
62	statistics & & \\
63	\addlinespace
64	Lexical & type--token ratio, hapax ratio, & 4 \\
65	diversity & bigram entropy, trigram entropy & \\
66	\addlinespace
67	Repetition & repeated 2/3/4-gram fractions & 3 \\
68	\bottomrule
69	\end{tabular}
70	\end{table}
71	
72	\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments (mean, variance, skewness, kurtosis) and quantiles (p10--p90); tail quantiles prove especially informative as recursive finetuning erodes the high-perplexity tail (\S\ref{sec:atlas}).
73	\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\log p(\text{token})$; surprisal variance captures second-order structure not redundant with perplexity moments.
74	\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.
75	\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \in \{2, 3, 4\}$.
76	
77	\subsection{Effective Discriminable Depth}
78	\label{sec:method:edd}
79	
80	Aggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.
81	We introduce the \emph{Effective Discriminable Depth} (EDD) to formalize the frontier beyond which adjacent depths become statistically indistinguishable.
82	
83	\paragraph{Pairwise discriminability.}
84	Let $\mathcal{D} = \{0, 1, \dots, K\}$ denote the depth set and $T \in (0.5, 1.0]$ a discrimination threshold.
85	For each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\lfloor\sqrt{19}\rfloor$ candidate features per split) trained on class-balanced data from $\mathbf{f}(x)$ (\S\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.
86	Each pair uses an independent classifier, avoiding the decision boundary dilution that arises in multi-class settings (\S\ref{sec:atlas:edd}).
87	
88	\begin{definition}[Effective Discriminable Depth]
89	\label{def:edd}
90	The \emph{Effective Discriminable Depth} at threshold $T$ is:
91	\begin{equation}
92	\mathrm{EDD}_T = \max \bigl\{ d^*{+}1 \,:\, \forall\, d' \leq d^*,\; \mathrm{AUC}(d', d'{+}1) \geq T \bigr\}
93	\label{eq:edd}
94	\end{equation}
95	where $d^* \in \{0, \dots, K{-}1\}$. If\, $\mathrm{AUC}(0,1) < T$, then $\mathrm{EDD}_T = 0$.
96	\end{definition}
97	
98	$\mathrm{EDD}_T$ is the deepest depth $d$ such that every adjacent pair from $(0,1)$ through $(d{-}1, d)$ remains discriminable at level $T$.
99	The universal quantifier ensures EDD reports the longest \emph{contiguous} discriminable prefix rather than an isolated high-AUC pair at greater depth.\footnote{Our AUC profiles are empirically monotonically decreasing for the 1--1.5B base models (\S\ref{sec:atlas}), so in practice $\mathrm{EDD}_T = \max\{d'{+}1 : \mathrm{AUC}(d', d'{+}1) \geq T\}$. Qwen2.5-7B exhibits a U-shaped AUC pattern rather than monotonic decay, possibly reflecting instruction-tuning effects (\S\ref{sec:gen:crossscale}). For non-monotonic profiles, the contiguous formulation is more conservative (see Limitations).}
100	We set $T{=}0.75$ as default; sensitivity at $T \in \{0.65, 0.70, 0.75, 0.80\}$ is reported in \S\ref{sec:atlas}.
101	
102	\paragraph{Classifiers.}
103	Our primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).
104	We compare against CORAL ordinal regression \cite{coral2020}, DivEye \cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \S\ref{sec:generalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "79ac53c9-163d-40a1-b402-1360acec471c",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "c9338dfd-7871-42b4-8e6f-8987ce60e9ae",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Problem Definition}\n\\label{sec:method:problem}\n\nLet $f_\\theta$ denote a language model and $\\mathcal{D}_0$ a corpus of human-written seed text.\nWe define a \\emph{recursive generation chain} of depth $K$ as the sequence $\\mathcal{D}_0, \\mathcal{D}_1, \\dots, \\mathcal{D}_K$, where each $\\mathcal{D}_k$ ($k \\geq 1$) is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$ and sampling from the resulting model.\nDepth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \\geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.\n\nGiven a text passage $x$, the task is to estimate its recursive generation depth $d \\in \\{0, 1, \\dots, K\\}$.\nThis is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.\n\n\\subsection{Multi-Generational Benchmark Construction}\n\\label{sec:method:benchmark}\n\nWe construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.\n\n\\paragraph{Model families.}\nWe select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).\nRestricting to a narrow parameter range isolates the effect of architecture and training data from scale.\n\n\\paragraph{Decoding strategies.}\nEach model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\nThese span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.\nOur findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.\n\n\\paragraph{Depth and scale.}\nThe primary benchmark covers depths d0--d3 across all $3 \\times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).\nFor depth extension experiments (\\S\\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.\n\n\\paragraph{Generation pipeline.}\nStarting from a Wikipedia subset as seed text ($\\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \\cite{hu2022lora} on $\\mathcal{D}_{k-1}$, freezing base model weights and training low-rank update matrices ($<$1\\% additional parameters; $r{=}16$, $\\alpha{=}32$, lr $2{\\times}10^{-4}$, batch size 8, 3 epochs, dropout $0.05$, architecture-specific targets); (2)~sampling 5{,}000 passages from the LoRA-finetuned model (max 512 tokens, BOS-seeded, no prompt conditioning) under the specified decoding strategy; (3)~the generated corpus becomes $\\mathcal{D}_k$ for the next cycle.\nEach depth is produced by a model explicitly trained on the prior depth's data---not by sampling from the unmodified base model.\nOur BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work.\nThere is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.\n\n\\paragraph{Reference model.}\nAll statistical features (\\S\\ref{sec:method:features}) are computed using Pythia-1.4B as fixed reference model, the smallest generator whose training corpus partially overlaps with the others.\nFor Pythia this constitutes self-model measurement, yet its accuracy (78.2\\%) does not exceed GPT-2~XL (85.4\\%), indicating no systematic self-model advantage.\nAn ablation with OLMo-1B as reference yields $\\Delta$=4.0pp (Appendix~\\ref{tab:ref_ablation}); further discussion in Limitations.\n\n\\subsection{Statistical Feature Design}\n\\label{sec:method:features}\n\nWe extract a feature vector $\\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\\S\\ref{sec:atlas:features}) shows the top 5 achieve 97.6\\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features, placing the effective independent dimensionality at ${\\approx}$4--5.\nThe features fall into four categories (Table~\\ref{tab:features}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{The 19 statistical features comprising $\\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}\n\\label{tab:features}\n\\begin{tabular}{@{}llr@{}}\n\\toprule\nCategory & Features & $n$ \\\\\n\\midrule\nPerplexity & mean, var, skewness, kurtosis, & 9 \\\\\nstatistics & p10, p25, p50, p75, p90 & \\\\\n\\addlinespace\nSurprisal & mean, var, entropy & 3 \\\\\nstatistics & & \\\\\n\\addlinespace\nLexical & type--token ratio, hapax ratio, & 4 \\\\\ndiversity & bigram entropy, trigram entropy & \\\\\n\\addlinespace\nRepetition & repeated 2/3/4-gram fractions & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments (mean, variance, skewness, kurtosis) and quantiles (p10--p90); tail quantiles prove especially informative as recursive finetuning erodes the high-perplexity tail (\\S\\ref{sec:atlas}).\n\\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\\log p(\\text{token})$; surprisal variance captures second-order structure not redundant with perplexity moments.\n\\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.\n\\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \\in \\{2, 3, 4\\}$.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:method:edd}\n\nAggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.\nWe introduce the \\emph{Effective Discriminable Depth} (EDD) to formalize the frontier beyond which adjacent depths become statistically indistinguishable.\n\n\\paragraph{Pairwise discriminability.}\nLet $\\mathcal{D} = \\{0, 1, \\dots, K\\}$ denote the depth set and $T \\in (0.5, 1.0]$ a discrimination threshold.\nFor each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\\lfloor\\sqrt{19}\\rfloor$ candidate features per split) trained on class-balanced data from $\\mathbf{f}(x)$ (\\S\\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.\nEach pair uses an independent classifier, avoiding the decision boundary dilution that arises in multi-class settings (\\S\\ref{sec:atlas:edd}).\n\n\\begin{definition}[Effective Discriminable Depth]\n\\label{def:edd}\nThe \\emph{Effective Discriminable Depth} at threshold $T$ is:\n\\begin{equation}\n\\mathrm{EDD}_T = \\max \\bigl\\{ d^*{+}1 \\,:\\, \\forall\\, d' \\leq d^*,\\; \\mathrm{AUC}(d', d'{+}1) \\geq T \\bigr\\}\n\\label{eq:edd}\n\\end{equation}\nwhere $d^* \\in \\{0, \\dots, K{-}1\\}$. If\\, $\\mathrm{AUC}(0,1) < T$, then $\\mathrm{EDD}_T = 0$.\n\\end{definition}\n\n$\\mathrm{EDD}_T$ is the deepest depth $d$ such that every adjacent pair from $(0,1)$ through $(d{-}1, d)$ remains discriminable at level $T$.\nThe universal quantifier ensures EDD reports the longest \\emph{contiguous} discriminable prefix rather than an isolated high-AUC pair at greater depth.\\footnote{Our AUC profiles are empirically monotonically decreasing for the 1--1.5B base models (\\S\\ref{sec:atlas}), so in practice $\\mathrm{EDD}_T = \\max\\{d'{+}1 : \\mathrm{AUC}(d', d'{+}1) \\geq T\\}$. Qwen2.5-7B exhibits a U-shaped AUC pattern rather than monotonic decay, possibly reflecting instruction-tuning effects (\\S\\ref{sec:gen:crossscale}). For non-monotonic profiles, the contiguous formulation is more conservative (see Limitations).}\nWe set $T{=}0.75$ as default; sensitivity at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ is reported in \\S\\ref{sec:atlas}.\n\n\\paragraph{Classifiers.}\nOur primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).\nWe compare against CORAL ordinal regression \\cite{coral2020}, DivEye \\cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \\S\\ref{sec:generalization}.",
      "numLines": 104,
      "startLine": 1,
      "totalLines": 104
    }
  },
  "sourceToolAssistantUUID": "79ac53c9-163d-40a1-b402-1360acec471c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-16T19:32:01.876Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Gp1XydH7aeuDSRmxw6NJAL`</summary>

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
  "parentUuid": "c9338dfd-7871-42b4-8e6f-8987ce60e9ae",
  "isSidechain": false,
  "requestId": "req_011Cb6ock5SVC6kgJjumgYj1",
  "type": "assistant",
  "uuid": "bc0f0076-42bb-4c5c-8d0b-3f8d2095cc86",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016UiAugdXeasjXoVt74g2ty",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13608,
      "cache_read_input_tokens": 30175,
      "output_tokens": 392,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13608,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 392,
          "cache_read_input_tokens": 30175,
          "cache_creation_input_tokens": 13608,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13608
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

_source line 48_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "5c7c35d8-d8a0-4ed5-b1bb-0205b7b74e4b",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 49_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Tool call

_source line 50 · 2026-05-16T19:32:07.520Z_

<details open><summary>🔧 Tool call — Read · `toolu_01YVQAnNCvw2YLVDugiGqrni`</summary>

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
  "parentUuid": "5c7c35d8-d8a0-4ed5-b1bb-0205b7b74e4b",
  "isSidechain": false,
  "requestId": "req_011Cb6odWCnPw9ErSHugxip9",
  "type": "assistant",
  "uuid": "e38afdd5-ffe3-4a82-b910-842153b53117",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R7Vs9CQ8KHNxRdAcLDLD9V",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8569,
      "cache_read_input_tokens": 43783,
      "output_tokens": 90,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8569,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 90,
          "cache_read_input_tokens": 43783,
          "cache_creation_input_tokens": 8569,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8569
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

_source line 51 · 2026-05-16T19:32:07.524Z_

<details><summary>↩ Tool result · `toolu_01YVQAnNCvw2YLVDugiGqrni`</summary>

```text
1	\section{Generalization and Robustness}
2	\label{sec:generalization}
3	
4	We test whether the atlas results (69.6--85.4\%) reflect genuine statistical regularities or training artifacts, evaluating generalization along seven axes: four in detail below---classifier choice (\S\ref{sec:gen:baselines}), cross-model transfer (\S\ref{sec:gen:crossmodel}), cross-strategy transfer (\S\ref{sec:gen:crossstrategy}), and preliminary cross-scale observations (\S\ref{sec:gen:crossscale})---and three in the Appendix (end-to-end learning, temperature robustness, and cross-boundary transfer).
5	
6	\subsection{Classifier Comparison and Surface-Text Ablation}
7	\label{sec:gen:baselines}
8	
9	Table~\ref{tab:baselines} evaluates three classifier families---bagging (RF), gradient boosting (XGBoost, LightGBM)---on the same 19 features across three atlas cells spanning the full accuracy range.
10	Per-cell spread is $\leq$0.4pp, establishing a feature-determined ceiling independent of the learning algorithm.
11	On Pythia nucleus, CORAL ordinal regression \cite{coral2020} (78.1\%) and DivEye \cite{diveye2026} (78.2\%) match the within-cell RF of Table~\ref{tab:main_matrix} within 0.1\,pp (bootstrap $p>0.05$, Bonferroni-corrected); all feature-based methods significantly outperform CE-MLP (74.9\%, $p<0.001$) and logistic regression (75.0\%).
12	
13	\paragraph{Surface-text ablation.}
14	Single-feature regression on mean perplexity performs at chance (25.1\%); two zero-shot LLMs---DeepSeek V3.2 (36.2\%) and Qwen2.5-7B-Instruct (30.4\%; each 500 samples, prompt in Appendix~\ref{app:zeroshot_prompt})---also fail, confirming that the depth signal resides in distributional statistics inaccessible from surface text alone (42\,pp gap vs.\ RF at 78.2\%).
15	
16	\begin{table}[t]
17	\centering
18	\small
19	\caption{Classifier convergence: 4-class accuracy (\%) across three atlas cells. RF (bagging), XGBoost and LightGBM (gradient boosting) operate on the same 19 features; $\Delta_{\max}$: largest per-cell spread. Chance = 25\%. RF values differ from Table~\ref{tab:main_matrix} by $\leq$0.7pp due to matched-fold evaluation.}
20	\label{tab:baselines}
21	\begin{tabular}{@{}lcccc@{}}
22	\toprule
23	Cell & RF & XGB & LGBM & $\Delta_{\max}$ \\
24	\midrule
25	Pythia, nuc. & 78.8 & 79.0 & 78.9 & 0.2 \\
26	GPT-2~XL, $\tau$ & 85.8 & 86.2 & 86.2 & 0.4 \\
27	Pythia, top-$k$ & 68.9 & 68.9 & 68.7 & 0.2 \\
28	\bottomrule
29	\end{tabular}
30	\end{table}
31	
32	Convergence across five structurally different classifiers---spanning bagging, gradient boosting, ordinal regression, and ensemble detection---confirms the signal resides in the features, not the learning algorithm.
33	Figure~\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread across d1--d3 under transfer.
34	
35	\begin{figure}[t]
36	\centering
37	\includegraphics[width=\columnwidth]{figures/fig_confusion_matrix.pdf}
38	\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\tau{=}0.9$, 85.4\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\%). d0 recall exceeds 99\% in both; errors spread across the d1--d3 range under transfer.}
39	\label{fig:confusion_matrix}
40	\end{figure}
41	
42	\subsection{Cross-Model Transfer}
43	\label{sec:gen:crossmodel}
44	
45	We perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\ref{tab:cross_model}).
46	
47	\begin{table}[t]
48	\centering
49	\small
50	\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\% / 33\% (d1--d3). d1--d3 bal.\ acc: Pythia 49.9\%, OLMo 59.2\%, GPT-2~XL 57.2\% (mean 55.4\%).}
51	\label{tab:cross_model}
52	\begin{tabular}{lccccc}
53	\toprule
54	Holdout & Acc & d0 & d1 & d2 & d3 \\
55	 & (\%) & Rec. & Rec. & Rec. & Rec. \\
56	\midrule
57	Pythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\
58	OLMo & \textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\
59	GPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\
60	\midrule
61	Mean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\
62	\bottomrule
63	\end{tabular}
64	\end{table}
65	
66	Mean transfer accuracy is 66.4\% (2.7$\times$ chance); d0 recall ($>$98\%) inflates the headline while d2 drops to 26.8\% (Pythia holdout).
67	Excluding d0, d1--d3 balanced accuracy averages 55.4\% (chance = 33\%).
68	
69	\subsection{Cross-Strategy Transfer}
70	\label{sec:gen:crossstrategy}
71	
72	We train on two decoding strategies and test on the held-out third (Table~\ref{tab:cross_strategy}).
73	
74	\begin{table}[t]
75	\centering
76	\small
77	\caption{Cross-strategy transfer (leave-one-out). Chance = 25\% / 33\% (d1--d3). d0 recall $\geq$89\% inflates headline; d1--d3 mean: 45.9\%.}
78	\label{tab:cross_strategy}
79	\begin{tabular}{lccc}
80	\toprule
81	Holdout & Pythia & OLMo & GPT-2 XL \\
82	 & Acc (\%) & Acc (\%) & Acc (\%) \\
83	\midrule
84	nucleus & \textbf{69.4} & \textbf{65.4} & \textbf{59.9} \\
85	temp ($\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\
86	top-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\
87	\bottomrule
88	\end{tabular}
89	\end{table}
90	
91	Mean cross-strategy accuracy (59.1\%) falls 7pp below cross-model transfer (66.4\%); excluding d0, d1--d3 accuracy drops to 45.9\% (chance = 33\%).
92	d2 recall varies sharply: nucleus holdouts retain 30--54\%, top-$k$ holdouts fall to 8--19\%, and temperature holdouts span 3.7--39.5\% (median 8.9\%).
93	Training on nucleus + top-$k$ and testing on temperature inverts the d1/d2 boundary (d1v2 AUC $<$ 0.5); per-strategy z-score normalization partially recovers it but leaves a residual gap (Limitations).
94	A multi-temperature ablation (Appendix~\ref{app:multi_tau}) confirms that within-$\tau$ depth signal holds for $\tau \leq 0.9$ (d1v2 AUC $>0.80$, accuracy within 3pp of $\tau{=}0.7$) but collapses at $\tau{=}1.1$; cross-$\tau$ LOO transfer (mean 46.7\%) is harder than cross-strategy transfer.
95	
96	End-to-end PLMs (DeBERTa-v3, RoBERTa) achieve only ${\sim}$59\%, lagging RF by 19pp, confirming depth signal resides in perplexity tail statistics inaccessible to standard PLM representations (Appendix~\ref{app:e2e}).
97	
98	%% ----------------------------------------------------------------
99	\subsection{Preliminary Cross-Scale Observations}
100	\label{sec:gen:crossscale}
101	
102	To test whether depth signal persists at larger scale, we extend the benchmark to Qwen2.5-7B-Instruct~\cite{qwen2.5} and Llama-3.1-8B-Instruct~\cite{llama3} under 4-bit NF4 QLoRA (nucleus $p{=}0.95$, 500 samples/depth, depths 0--5).
103	Both models exceed chance: Llama-3.1-8B achieves 70.2\% (95\% CI $[68.3, 72.4]$, $\mathrm{EDD}_{0.70}{=}4$) and Qwen2.5-7B 60.1\% ($[58.0, 62.1]$, $\mathrm{EDD}_{0.70}{>}5$), with weaker per-step signal than 1--1.5B models (mean consecutive AUC ${\approx}$0.78 vs.\ 0.85).
104	The two instruction-tuned models exhibit divergent AUC trajectories: Llama-3.1-8B decays monotonically (consistent with 1--1.5B), while Qwen2.5-7B shows a U-shaped recovery.
105	
106	\paragraph{Base vs.\ Instruction-Tuned Control.}
107	A base-model control (Llama-3.1-8B, no instruction tuning) achieves 59.9\% four-class accuracy (95\% CI [57.8, 62.15]) with non-monotonic AUC decay ($d_{2{\text{v}}3}=0.682 \to d_{3{\text{v}}4}=0.730$, a U-shaped recovery), while the instruction-tuned variant reaches 70.2\% with strictly monotonic decay. This suggests instruction-tuning \emph{regularizes} recursive degradation patterns---making depth signal stronger and more predictable---rather than introducing confounding artifacts. The four remaining cross-scale caveats (quantization, reduced $n$, single strategy, vocabulary mismatch) apply equally to both variants.
108	
109	Four confounds (quantization, reduced $n$, single strategy, vocabulary mismatch) limit causal attribution; full results including per-pair AUC tables appear in Appendix~\ref{app:cross_scale_full}.
110	Cross-model recursive chains (84.75\%), validated by a reverse-chain control (85.75\%; Appendix~\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\%) further confirm signal universality.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e38afdd5-ffe3-4a82-b910-842153b53117",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "0dc15aa4-b6f9-45b1-a769-ad27b0cd3d61",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
      "content": "\\section{Generalization and Robustness}\n\\label{sec:generalization}\n\nWe test whether the atlas results (69.6--85.4\\%) reflect genuine statistical regularities or training artifacts, evaluating generalization along seven axes: four in detail below---classifier choice (\\S\\ref{sec:gen:baselines}), cross-model transfer (\\S\\ref{sec:gen:crossmodel}), cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}), and preliminary cross-scale observations (\\S\\ref{sec:gen:crossscale})---and three in the Appendix (end-to-end learning, temperature robustness, and cross-boundary transfer).\n\n\\subsection{Classifier Comparison and Surface-Text Ablation}\n\\label{sec:gen:baselines}\n\nTable~\\ref{tab:baselines} evaluates three classifier families---bagging (RF), gradient boosting (XGBoost, LightGBM)---on the same 19 features across three atlas cells spanning the full accuracy range.\nPer-cell spread is $\\leq$0.4pp, establishing a feature-determined ceiling independent of the learning algorithm.\nOn Pythia nucleus, CORAL ordinal regression \\cite{coral2020} (78.1\\%) and DivEye \\cite{diveye2026} (78.2\\%) match the within-cell RF of Table~\\ref{tab:main_matrix} within 0.1\\,pp (bootstrap $p>0.05$, Bonferroni-corrected); all feature-based methods significantly outperform CE-MLP (74.9\\%, $p<0.001$) and logistic regression (75.0\\%).\n\n\\paragraph{Surface-text ablation.}\nSingle-feature regression on mean perplexity performs at chance (25.1\\%); two zero-shot LLMs---DeepSeek V3.2 (36.2\\%) and Qwen2.5-7B-Instruct (30.4\\%; each 500 samples, prompt in Appendix~\\ref{app:zeroshot_prompt})---also fail, confirming that the depth signal resides in distributional statistics inaccessible from surface text alone (42\\,pp gap vs.\\ RF at 78.2\\%).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Classifier convergence: 4-class accuracy (\\%) across three atlas cells. RF (bagging), XGBoost and LightGBM (gradient boosting) operate on the same 19 features; $\\Delta_{\\max}$: largest per-cell spread. Chance = 25\\%. RF values differ from Table~\\ref{tab:main_matrix} by $\\leq$0.7pp due to matched-fold evaluation.}\n\\label{tab:baselines}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & RF & XGB & LGBM & $\\Delta_{\\max}$ \\\\\n\\midrule\nPythia, nuc. & 78.8 & 79.0 & 78.9 & 0.2 \\\\\nGPT-2~XL, $\\tau$ & 85.8 & 86.2 & 86.2 & 0.4 \\\\\nPythia, top-$k$ & 68.9 & 68.9 & 68.7 & 0.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nConvergence across five structurally different classifiers---spanning bagging, gradient boosting, ordinal regression, and ensemble detection---confirms the signal resides in the features, not the learning algorithm.\nFigure~\\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread across d1--d3 under transfer.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_confusion_matrix.pdf}\n\\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\\tau{=}0.9$, 85.4\\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\\%). d0 recall exceeds 99\\% in both; errors spread across the d1--d3 range under transfer.}\n\\label{fig:confusion_matrix}\n\\end{figure}\n\n\\subsection{Cross-Model Transfer}\n\\label{sec:gen:crossmodel}\n\nWe perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\\ref{tab:cross_model}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\\% / 33\\% (d1--d3). d1--d3 bal.\\ acc: Pythia 49.9\\%, OLMo 59.2\\%, GPT-2~XL 57.2\\% (mean 55.4\\%).}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nHoldout & Acc & d0 & d1 & d2 & d3 \\\\\n & (\\%) & Rec. & Rec. & Rec. & Rec. \\\\\n\\midrule\nPythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\\\\nOLMo & \\textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\\\\nGPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\\\\n\\midrule\nMean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean transfer accuracy is 66.4\\% (2.7$\\times$ chance); d0 recall ($>$98\\%) inflates the headline while d2 drops to 26.8\\% (Pythia holdout).\nExcluding d0, d1--d3 balanced accuracy averages 55.4\\% (chance = 33\\%).\n\n\\subsection{Cross-Strategy Transfer}\n\\label{sec:gen:crossstrategy}\n\nWe train on two decoding strategies and test on the held-out third (Table~\\ref{tab:cross_strategy}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-strategy transfer (leave-one-out). Chance = 25\\% / 33\\% (d1--d3). d0 recall $\\geq$89\\% inflates headline; d1--d3 mean: 45.9\\%.}\n\\label{tab:cross_strategy}\n\\begin{tabular}{lccc}\n\\toprule\nHoldout & Pythia & OLMo & GPT-2 XL \\\\\n & Acc (\\%) & Acc (\\%) & Acc (\\%) \\\\\n\\midrule\nnucleus & \\textbf{69.4} & \\textbf{65.4} & \\textbf{59.9} \\\\\ntemp ($\\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\\\\ntop-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean cross-strategy accuracy (59.1\\%) falls 7pp below cross-model transfer (66.4\\%); excluding d0, d1--d3 accuracy drops to 45.9\\% (chance = 33\\%).\nd2 recall varies sharply: nucleus holdouts retain 30--54\\%, top-$k$ holdouts fall to 8--19\\%, and temperature holdouts span 3.7--39.5\\% (median 8.9\\%).\nTraining on nucleus + top-$k$ and testing on temperature inverts the d1/d2 boundary (d1v2 AUC $<$ 0.5); per-strategy z-score normalization partially recovers it but leaves a residual gap (Limitations).\nA multi-temperature ablation (Appendix~\\ref{app:multi_tau}) confirms that within-$\\tau$ depth signal holds for $\\tau \\leq 0.9$ (d1v2 AUC $>0.80$, accuracy within 3pp of $\\tau{=}0.7$) but collapses at $\\tau{=}1.1$; cross-$\\tau$ LOO transfer (mean 46.7\\%) is harder than cross-strategy transfer.\n\nEnd-to-end PLMs (DeBERTa-v3, RoBERTa) achieve only ${\\sim}$59\\%, lagging RF by 19pp, confirming depth signal resides in perplexity tail statistics inaccessible to standard PLM representations (Appendix~\\ref{app:e2e}).\n\n%% ----------------------------------------------------------------\n\\subsection{Preliminary Cross-Scale Observations}\n\\label{sec:gen:crossscale}\n\nTo test whether depth signal persists at larger scale, we extend the benchmark to Qwen2.5-7B-Instruct~\\cite{qwen2.5} and Llama-3.1-8B-Instruct~\\cite{llama3} under 4-bit NF4 QLoRA (nucleus $p{=}0.95$, 500 samples/depth, depths 0--5).\nBoth models exceed chance: Llama-3.1-8B achieves 70.2\\% (95\\% CI $[68.3, 72.4]$, $\\mathrm{EDD}_{0.70}{=}4$) and Qwen2.5-7B 60.1\\% ($[58.0, 62.1]$, $\\mathrm{EDD}_{0.70}{>}5$), with weaker per-step signal than 1--1.5B models (mean consecutive AUC ${\\approx}$0.78 vs.\\ 0.85).\nThe two instruction-tuned models exhibit divergent AUC trajectories: Llama-3.1-8B decays monotonically (consistent with 1--1.5B), while Qwen2.5-7B shows a U-shaped recovery.\n\n\\paragraph{Base vs.\\ Instruction-Tuned Control.}\nA base-model control (Llama-3.1-8B, no instruction tuning) achieves 59.9\\% four-class accuracy (95\\% CI [57.8, 62.15]) with non-monotonic AUC decay ($d_{2{\\text{v}}3}=0.682 \\to d_{3{\\text{v}}4}=0.730$, a U-shaped recovery), while the instruction-tuned variant reaches 70.2\\% with strictly monotonic decay. This suggests instruction-tuning \\emph{regularizes} recursive degradation patterns---making depth signal stronger and more predictable---rather than introducing confounding artifacts. The four remaining cross-scale caveats (quantization, reduced $n$, single strategy, vocabulary mismatch) apply equally to both variants.\n\nFour confounds (quantization, reduced $n$, single strategy, vocabulary mismatch) limit causal attribution; full results including per-pair AUC tables appear in Appendix~\\ref{app:cross_scale_full}.\nCross-model recursive chains (84.75\\%), validated by a reverse-chain control (85.75\\%; Appendix~\\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\\%) further confirm signal universality.",
      "numLines": 110,
      "startLine": 1,
      "totalLines": 110
    }
  },
  "sourceToolAssistantUUID": "e38afdd5-ffe3-4a82-b910-842153b53117",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 52 · 2026-05-16T19:32:56.826Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me check the specific issues:

1. **R3-N4** 'Universal' overclaim - Line 14 of introduction.tex says "universal and scale-variant across the three model families and three decoding strategies studied" — wait, let me look again. It says "**universal and scale-variant** across the three model families and three decoding strategies studied." The word "universal" is still there but it's qualified with the scope. Let me check other occurrences in abstract/discussion.

Looking at abstract.tex line 6: "perplexity tail statistics emerging as consistent depth markers across all studied configurations" — good, uses "consistent" here.


I'm finding more instances of "universal" and "universality" scattered through the paper. In introduction.tex line 14, the term is still present though qualified by scope. Generalization.tex line 110 uses "signal universality" directly, and I need to scan the discussion and conclusion sections to see how widespread this issue is.

2. **R1-W2** d0 inflation — Abstract line 7 mentions "Cross-model transfer reaches 66.4\% (d1" but the sentence appears to cut off mid-thought.

3. **R4-W1** Curation PoC — The discussion mentions "depth-graduated data curation" with a reference to the appendix, but when I check the contribution list in introduction.tex, curation isn't listed as a main contribution—it's only presented as an application in the discussion section. I need to verify whether the paper characterizes this as an inconclusive pilot or something more definitive.

4. **R4-W3** Theory connection — I should look for any theoretical analysis that connects to model collapse theory.

5. **R5-N1** Perplexity tail dominance novelty vs Dohmatob (2024) — The introduction mentions that first-generation synthetic text may be benign or beneficial, while deeply recursive text causes distributional collapse that degrades quality, citing Dohmatob (2024). I need to check how this relates to the novelty claim about perplexity tail dominance.

Looking at the Related Work section, I see the paper distinguishes itself by addressing the inverse problem of estimating depth from text alone, whereas prior work assumes depth is known. Dohmatob's work predicts tail erosion under recursive training theoretically, while this paper uses tail statistics for depth estimation as an applied contribution. But I should verify if this distinction is made explicit in the Introduction or Related Work sections.

6. **R5-W4** Missing references — I'm checking whether Schaeffer et al. (2025), Frank & Hall (2001), and Rennie & Srebro (2005) have been added to the paper. Looking at the ordinal classification section in the related work, I see CORAL is cited...

I notice the references for Frank & Hall and Rennie & Srebro aren't present in the bibliography, and Schaeffer et al. (2025) doesn't have its own entry either.

7. **R3-M1** Citation metadata issue — the DeBERTa v3 reference has a mismatch where the citation key says "2021" but the year field shows 2023, even though the paper was originally on arxiv in 2021.

For the Alemohammad paper, the author list checks out correctly against the arXiv version. So the real problem is just that DeBERTa citation key being misleading about the actual publication year. The author names are definitely wrong — "Romero, Oscar" should be "Leong, Oscar" and "Ramanarayanan, Sriram" should be "Rangamani, Akshay". Looking at the abstract now, I'm noticing it's packed with numbers — I count over twenty different metrics and values scattered throughout, which makes it quite dense. Let me check the appendix to see how the curation proof of concept is documented.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0dc15aa4-b6f9-45b1-a769-ad27b0cd3d61",
  "isSidechain": false,
  "requestId": "req_011Cb6odvCfocnPbJghCcBkE",
  "type": "assistant",
  "uuid": "70460c1d-d1ef-43cf-b360-56e0ce6d4236",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KpArLTP832nrXXbPyXy1aN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3274,
      "cache_read_input_tokens": 52352,
      "output_tokens": 1888,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3274,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1888,
          "cache_read_input_tokens": 52352,
          "cache_creation_input_tokens": 3274,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3274
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

_source line 53 · 2026-05-16T19:32:56.961Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DHrq5Te2gPVvek8oZdoeEf`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "70460c1d-d1ef-43cf-b360-56e0ce6d4236",
  "isSidechain": false,
  "requestId": "req_011Cb6odvCfocnPbJghCcBkE",
  "type": "assistant",
  "uuid": "50e80fb4-1edb-4c86-ab40-91f3e14a5334",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KpArLTP832nrXXbPyXy1aN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3274,
      "cache_read_input_tokens": 52352,
      "output_tokens": 1888,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3274,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1888,
          "cache_read_input_tokens": 52352,
          "cache_creation_input_tokens": 3274,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3274
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

_source line 54_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "50e80fb4-1edb-4c86-ab40-91f3e14a5334",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 55_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Tool result

_source line 56 · 2026-05-16T19:32:57.257Z_

<details><summary>↩ Tool result · `toolu_01DHrq5Te2gPVvek8oZdoeEf`</summary>

```text
1	\section{Additional Results}
2	\label{app:additional}
3	
4	\subsection{Top-$k$ Feature Trajectories}
5	\label{app:topk_trajectories}
6	
7	Figure~\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\tau{=}0.9$) sampling.
8	Top-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \S\ref{sec:atlas:strategy}.
9	Concretely, the d0$\to$d1 drop in \textsc{p90\_ppl} under top-$k$ is 78\% (vs.\ 87\% for nucleus), and the d2$\to$d3 reduction is 31\% (vs.\ 39\% for nucleus).
10	Despite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.
11	
12	\subsection{Permutation Importance}
13	\label{app:permutation}
14	
15	To verify that the Gini-based importance rankings in \S\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.
16	The top-2 features are stable across measures: \textsc{p90\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \textsc{var\_surprisal} in 8/9 (vs.\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \textsc{p75\_ppl} displaces \textsc{var\_surprisal} to rank 3).
17	Kendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).
18	Pairwise Spearman correlations are: SHAP--Gini $\rho{=}0.93$, SHAP--permutation $\rho{=}0.84$, Gini--permutation $\rho{=}0.76$.
19	Per-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.
20	
21	\subsection{Per-Class Recall}
22	\label{app:per_class}
23	
24	Table~\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).
25	Depth~0 recall exceeds 98\% uniformly.
26	Among generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.
27	
28	\begin{table}[h]
29	\centering
30	\small
31	\caption{Per-class recall (\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}
32	\label{tab:per_class_recall}
33	\begin{tabular}{@{}lcccc@{}}
34	\toprule
35	Cell & d0 & d1 & d2 & d3 \\
36	\midrule
37	Pythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\
38	Pythia, $\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\
39	Pythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\
40	OLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\
41	OLMo, $\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\
42	OLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\
43	GPT-2~XL, nuc.     & 99.2 & 85.9 & \textbf{73.3} & 77.5 \\
44	GPT-2~XL, $\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\
45	GPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\
46	\bottomrule
47	\end{tabular}
48	\end{table}
49	
50	\subsection{DCOL Iteration Details}
51	\label{app:dcol_iterations}
52	
53	Table~\ref{tab:dcol_iterations} summarizes all six DCOL iterations.
54	DeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.
55	
56	\begin{table}[h]
57	\centering
58	\small
59	\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\%.}
60	\label{tab:dcol_iterations}
61	\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}
62	\toprule
63	Ver. & Backbone & Config & Outcome \\
64	\midrule
65	v1 & DeBERTa & FT, m\_lr $10^{-3}$ & Embed.\ collapse (31.5\%) \\
66	v2 & DeBERTa & FT, m\_lr $10^{-4}$ & OOM \\
67	v3 & DeBERTa & FT, m\_lr $10^{-4}$ & Forgetting + OOM \\
68	v4 & DeBERTa & LoRA, m\_lr $10^{-3}$ & Embed.\ collapse \\
69	v5 & DeBERTa & LoRA, m\_lr $10^{-4}$ & NaN gradients \\
70	v6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\% ($-$13.7pp) \\
71	\bottomrule
72	\end{tabular}
73	\end{table}
74	
75	\subsection{Zero-Shot LLM Prompt Template}
76	\label{app:zeroshot_prompt}
77	
78	Both DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.
79	The system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).
80	The user message presents the passage (truncated to ${\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.
81	No in-context examples are provided.
82	
83	\begin{quote}
84	\small
85	\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\ldots]''
86	
87	\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \{text\}. Respond with ONLY a JSON object: \{\texttt{"depth"}: $\langle$int 0--3$\rangle$, \texttt{"confidence"}: $\langle$float 0--1$\rangle$, \texttt{"reasoning"}: $\langle$str$\rangle$\}''
88	\end{quote}
89	
90	\subsection{Temperature Robustness}
91	\label{app:multi_tau}
92	
93	The cross-strategy results in \S\ref{sec:gen:crossstrategy} use a single temperature ($\tau{=}0.9$).
94	To test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\tau \in \{0.5, 0.7, 0.9, 1.1\}$ on Pythia-1.4B.
95	
96	\paragraph{Within-$\tau$ robustness.}
97	For $\tau \in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\% to 77.3\% (Table~\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.
98	The same top-5 features (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{mean\_surprisal}, \texttt{p75\_ppl}) dominate across all $\tau$ values with only minor rank-order variation.
99	
100	\paragraph{Collapse at $\tau{=}1.1$: memorization as prerequisite.}
101	At $\tau{=}1.1$, 4-class accuracy drops to 57.2\% and d1v2 AUC falls to 0.528.
102	Training loss reveals the mechanism: at low temperature ($\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \to 0.42 \to 0.16$), indicating rapid memorization of the model's own output.
103	At $\tau{=}1.1$, loss remains nearly flat ($2.27 \to 1.91 \to 1.85$)---high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.
104	This establishes \emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.
105	
106	\paragraph{Cross-$\tau$ non-transferability.}
107	Leave-one-$\tau$-out transfer yields mean accuracy of 46.7\% with mean d1v2 AUC of 0.319 (Table~\ref{tab:multi_tau_cross})---worse than cross-strategy transfer (59.1\%; \S\ref{sec:gen:crossstrategy}).
108	Holdout $\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.
109	This extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific, reinforcing the need for strategy-conditioned classifiers.
110	
111	\paragraph{Ecological validity.}
112	On WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity---partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.
113	On noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.
114	
115	\begin{table}[h]
116	\centering
117	\small
118	\caption{Within-$\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\ depth $j$.}
119	\label{tab:multi_tau_within}
120	\begin{tabular}{@{}lcccc@{}}
121	\toprule
122	$\tau$ & 4-class acc (\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\
123	\midrule
124	0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\
125	0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\
126	0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\
127	1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\
128	\bottomrule
129	\end{tabular}
130	\end{table}
131	
132	\begin{table}[h]
133	\centering
134	\small
135	\caption{Cross-$\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}
136	\label{tab:multi_tau_cross}
137	\begin{tabular}{@{}lcc@{}}
138	\toprule
139	Holdout & Acc (\%) & d1v2 AUC \\
140	\midrule
141	$\tau{=}0.5$ & 52.2 & 0.176 \\
142	$\tau{=}0.7$ & 41.0 & 0.299 \\
143	$\tau{=}0.9$ & 46.4 & 0.277 \\
144	$\tau{=}1.1$ & 47.1 & 0.525 \\
145	\midrule
146	Mean & 46.7 & 0.319 \\
147	\bottomrule
148	\end{tabular}
149	\end{table}
150	
151	\subsection{Feature Overlap Analysis}
152	\label{app:feature_overlap}
153	
154	We probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.
155	PLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics---\textsc{var\_surprisal} and \textsc{p90\_ppl} yield negative $R^2$ under linear probing, indicating these features are not linearly accessible in the pretrained representation space.
156	This confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\S\ref{app:e2e}) stems from complementary---not redundant---representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.
157	
158	\subsection{End-to-End Learning}
159	\label{app:e2e}
160	
161	DeBERTa-v3-base \cite{he2021_deberta_v3} and RoBERTa-base \cite{liu2019_roberta} finetuned end-to-end achieve 58.3\% ($\pm$4.7\%) and 59.5\% ($\pm$3.2\%) respectively---lagging the RF baseline (78.2\%) by 19.9pp and 18.7pp.
162	The 1.2pp inter-backbone gap rules out architecture bias; Table~\ref{tab:e2e_detail} shows both backbones share the same failure mode---high d0 F1 ($>$0.94) but collapsed d1/d2 performance (F1 $\leq$ 0.42)---while RF achieves 0.596 d2 recall, a $>$2$\times$ advantage at the hardest depth class.
163	
164	\begin{table}[h]
165	\centering
166	\small
167	\caption{Per-class performance for end-to-end PLM classifiers vs.\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}
168	\label{tab:e2e_detail}
169	\begin{tabular}{@{}lccccc@{}}
170	\toprule
171	Method & Acc (\%) & d0 & d1 & d2 & d3 \\
172	\midrule
173	DeBERTa-v3 & 58.3\,$\pm$\,4.7 & .947 & .378 & .247 & .656 \\
174	RoBERTa-base & 59.5\,$\pm$\,3.2 & .958 & .416 & .261 & .647 \\
175	\midrule
176	RF (19 feat.) & 78.2 & --- & --- & .596$^\dagger$ & --- \\
177	\bottomrule
178	\multicolumn{6}{@{}l}{\footnotesize $^\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}
179	\end{tabular}
180	\end{table}
181	
182	\paragraph{Feature space divergence.}
183	SHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\% of RF's total contribution.
184	Three independent importance measures---SHAP, Gini, and permutation---show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \S\ref{app:permutation}), with \texttt{p90\_ppl} appearing in the SHAP top-2 in 9/9 cells and \texttt{var\_surprisal} in 8/9.
185	Linear probing of PLM [CLS] representations yields negative $R^2$ for both \texttt{var\_surprisal} and \texttt{p90\_ppl} (\S\ref{app:feature_overlap}), indicating that pretrained representations lack the linear structure needed to recover perplexity tail statistics---a systematic representational gap rather than a backbone-specific artifact.
186	
187	DCOL \cite{cloc2025} reached 64.5\% (\S\ref{app:dcol_iterations}); all end-to-end approaches (58--65\%) underperform feature-based methods, suggesting depth estimation benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.
188	This comparison is bounded by backbone scale ($\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.
189	
190	\subsection{Domain Bias Analysis}
191	\label{app:domain_bias}
192	
193	To assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.
194	
195	\paragraph{Methodological note.}
196	An initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\%, seed-group prediction 20.8\%).
197	We discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.
198	The results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.
199	
200	\paragraph{Sub-A: Standard CV.}
201	Five-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\% to 82\% across the 9 atlas cells (up to 2.5$\times$ above the 33.3\% chance level), confirming that depth signal is the dominant classification factor.
202	
203	\paragraph{Sub-B: LOGO evaluation.}
204	We assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.
205	LOGO mean accuracy is 72.1\% (range 59.5--81.6\%), matching standard CV (72.0\%) within noise (before fix: 64.0\%, reflecting the depth--group confound).
206	Per-cell fold standard deviations range from 0.4pp to 1.4pp, indicating that cross-group generalization is as reliable as within-group classification.
207	
208	\paragraph{Sub-C: Negative control.}
209	We train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\%).
210	Depth prediction accuracy averages 72.0\%; seed-group prediction averages 10.2\%---indistinguishable from chance (before fix: 20.8\%, inflated by the depth--group confound).
211	The depth-to-seed-group accuracy ratio is 7.1$\times$, confirming that the feature representation encodes depth but not seed-article identity.
212	
213	Taken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.
214	
215	\subsection{Wild-Data Calibration}
216	\label{app:calibration}
217	
218	Table~\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).
219	
220	\begin{table}[h]
221	\centering
222	\small
223	\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\% Wilson CIs computed for C4 ($n{=}5{,}000$).}
224	\label{tab:calibration}
225	\begin{tabular}{@{}llrccc@{}}
226	\toprule
227	Model & Source & $n$ & d0 (\%) & FPR (\%) & 95\% Wilson CI \\
228	\midrule
229	Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\
230	 & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\
231	\addlinespace
232	GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\
233	 & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\
234	\addlinespace
235	OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\
236	 & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\
237	\bottomrule
238	\end{tabular}
239	\end{table}
240	
241	On WikiText-103, all three classifiers achieve $\geq$98.5\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.
242	On C4, FPR varies sharply: OLMo (4.7\%) vs.\ Pythia (20.2\%) and GPT-2~XL (22.4\%).
243	C4 misclassifications concentrate in template and SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0 passages), rather than in random noise.
244	The model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.
245	Among C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\%), d2 (3.7\%), d3 (9.6\%); for OLMo, d1 (2.9\%), d2 (0.5\%), d3 (1.3\%)---the non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.
246	
247	\subsection{Downstream Curation PoC}
248	\label{app:curation_poc}
249	
250	To validate that depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.
251	We fine-tune Pythia-410M with LoRA ($r{=}16$, $\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.
252	Conditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\approx$25\%, moderate $\approx$50\%, soft threshold).
253	Table~\ref{tab:curation_poc} reports per-condition perplexity; Table~\ref{tab:curation_comparisons} reports pairwise contrasts.
254	
255	\begin{table}[h]
256	\centering
257	\small
258	\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\,: $p<0.05$ (paired $t$-test vs.\ unfiltered).}
259	\label{tab:curation_poc}
260	\resizebox{\columnwidth}{!}{%
261	\begin{tabular}{@{}lcccccc@{}}
262	\toprule
263	Condition & Mean PPL & Std & $n$ & $\Delta$ vs Unfilt. & $p$ & $d_z$ \\
264	\midrule
265	unfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\
266	rf\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\
267	rf\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\
268	rf\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\
269	oracle\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\
270	oracle\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\
271	random\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\
272	random\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\
273	random\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\
274	\bottomrule
275	\end{tabular}}
276	\end{table}
277	
278	\begin{table}[h]
279	\centering
280	\small
281	\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\,: $p<0.05$; $^{**}$\,: $p<0.01$.}
282	\label{tab:curation_comparisons}
283	\begin{tabular}{@{}lccc@{}}
284	\toprule
285	Comparison & $\Delta$ PPL & $t$ & $p$ \\
286	\midrule
287	rf\_strict vs random\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\
288	rf\_moderate vs random\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\
289	rf\_soft vs random\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\
290	rf\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\
291	\bottomrule
292	\end{tabular}
293	\end{table}
294	
295	\subsection{Reference Model Ablation}
296	\label{app:ref_ablation}
297	
298	\begin{table}[h]
299	\centering
300	\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}
301	\label{tab:ref_ablation}
302	\begin{tabular}{lcc}
303	\toprule
304	Reference Model & Architecture & Accuracy (\%) \\
305	\midrule
306	Pythia-1.4B (self) & GPT-NeoX & 78.6 $\pm$ 0.6 \\
307	OLMo-1B (cross) & OLMo & 74.5 $\pm$ 0.7 \\
308	\bottomrule
309	\end{tabular}
310	\end{table}
311	
312	\subsection{Cross-Scale Full Results}
313	\label{app:cross_scale_full}
314	
315	This section provides the full cross-scale analysis summarized in \S\ref{sec:gen:crossscale}.
316	We extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \in \{0, 1, \ldots, 5\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).
317	Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.
318	
319	\paragraph{Scale comparison.}
320	Table~\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).
321	
322	\begin{table}[h]
323	\centering
324	\small
325	\caption{Cross-scale comparison: 4-class RF accuracy (\%, depths 0--3, nucleus), $\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\% bootstrap. Chance = 25\%.}
326	\label{tab:cross_scale}
327	\begin{tabular}{@{}lccc@{}}
328	\toprule
329	Model & 4-class acc & $\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\
330	\midrule
331	GPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\
332	OLMo-1B & 78.8 & 4 & 0.997 \\
333	Pythia-1.4B & 78.2 & 4 & 0.998 \\
334	\midrule
335	Llama-3.1-8B & 70.2\,[68.3, 72.4] & 4 & 0.949 \\
336	Qwen2.5-7B & 60.1\,[58.0, 62.1] & ${>}5$ & 0.969 \\
337	\bottomrule
338	\end{tabular}
339	\end{table}
340	
341	\paragraph{(1) Depth signal persists at 7--8B scale.}
342	Both 7--8B models substantially exceed the 25\% chance baseline: Llama-3.1-8B achieves 70.2\% (95\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\% ($[58.0, 62.1]$), confirming that recursive depth remains estimable from perplexity-based features even when the generator is 5--7$\times$ larger than the reference model.
343	Depth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).
344	
345	\paragraph{(2) EDD at 7--8B scale.}
346	At threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\ref{tab:cross_scale_auc}), yielding $\mathrm{EDD}_{T{=}0.70} > 5$---exceeding the $\mathrm{EDD}{=}4$ observed at 1--1.5B.
347	Llama-3.1-8B matches the smaller models at $\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.
348	Both larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\ 0.852 at 1--1.5B).
349	
350	\begin{table}[h]
351	\centering
352	\small
353	\caption{Consecutive binary AUC for 7--8B models (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a non-monotonic (U-shaped) pattern with all pairs above $T$.}
354	\label{tab:cross_scale_auc}
355	\begin{tabular}{@{}lccccc@{}}
356	\toprule
357	Model & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\
358	\midrule
359	Llama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\
360	Qwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\
361	\bottomrule
362	\end{tabular}
363	\end{table}
364	
365	\paragraph{(3) Divergent AUC trajectories and instruction-tuning effect.}
366	Among instruction-tuned models, Llama-3.1-8B exhibits monotonic AUC decay consistent with the 1--1.5B pattern, while Qwen2.5-7B shows a U-shaped recovery beyond d2v3 (Table~\ref{tab:cross_scale_auc}).
367	A base-model control (Llama-3.1-8B without instruction tuning) clarifies the causal direction: the base model achieves 59.9\% four-class accuracy (95\% CI [57.8, 62.15], $\mathrm{EDD}_{0.70}{=}2$) with non-monotonic AUC decay (Table~\ref{tab:llama3_base_auc}), while the instruction-tuned variant reaches 70.2\% with strictly monotonic decay.
368	The base-model control experiment suggests instruction-tuning regularizes rather than confounds the depth signal.
369	
370	\begin{table}[h]
371	\centering
372	\small
373	\caption{Pairwise AUC: Llama-3.1-8B Base vs.\ Instruct.}
374	\label{tab:llama3_base_auc}
375	\begin{tabular}{lccccc}
376	\toprule
377	Variant & $d_{0\text{v}1}$ & $d_{1\text{v}2}$ & $d_{2\text{v}3}$ & $d_{3\text{v}4}$ & $d_{4\text{v}5}$ \\
378	\midrule
379	Base & 0.918 & 0.794 & 0.682 & 0.730 & 0.595 \\
380	Instruct & 0.965 & 0.874 & 0.771 & 0.716 & 0.618 \\
381	\bottomrule
382	\end{tabular}
383	\end{table}
384	
385	The base model exhibits non-monotonic decay with a U-shaped recovery at $d_{3\text{v}4}$, while the instruction-tuned variant shows strictly monotonic decay. Both variants exceed chance (AUC $> 0.5$) at all boundaries, confirming depth signal exists regardless of instruction-tuning, though instruction-tuning strengthens and regularizes it.
386	
387	\paragraph{Caveats.}
388	For Qwen2.5-7B, the CI lower bound (58.0\%) does not exclude sub-60\% accuracy; Llama-3.1-8B's lower bound (68.3\%) is more comfortably above chance but still below the 75--83\% range at 1--1.5B.
389	The divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.
390	
391	\paragraph{Confounds.}
392	\label{app:cross_scale_confounds}
393	Four confounds limit these results: (1)~4-bit NF4 QLoRA quantization (absent at 1--1.5B) may distort the perplexity distribution independently of depth; (2)~smaller sample size (500 vs.\ 5{,}000 per depth) widens confidence intervals; (3)~evaluation is limited to nucleus sampling, leaving other strategies untested at this scale; (4)~vocabulary mismatch between 7--8B generators and the 1.4B reference model.
394	The base-model control partially addresses a former confound (instruction-tuning): since the base variant shows weaker signal with non-monotonic decay while the instruction-tuned variant shows stronger monotonic signal, instruction-tuning regularizes rather than confounds depth estimation.
395	The remaining confounds are not mutually independent---quantization and vocabulary mismatch both affect the perplexity distribution---making it infeasible to attribute the observed accuracy gap (60--70\% vs.\ 78--85\% at 1--1.5B) to any single factor.
396	
397	\subsection{Cross-Boundary Generalization}
398	\label{app:cross_boundary}
399	
400	The preceding experiments assume a single model family generates all recursive depths.
401	In practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.
402	We probe whether the depth signal persists under two relaxations of the single-model assumption.
403	
404	\paragraph{Cross-model recursive chains.}
405	We construct a heterogeneous chain: human text (d0) $\to$ Pythia-1.4B generates d1 $\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.
406	Each recursive step uses a \emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.
407	A 4-class Random Forest achieves 84.75\% accuracy (95\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).
408	Pairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.
409	These results suggest that distributional artifacts of recursive generation persist across model boundaries---providing preliminary evidence consistent with a process-level depth signal rather than individual generator artifacts.
410	
411	\paragraph{Confound discussion.}
412	The heterogeneous chain confounds architecture identity with depth (d1=Pythia, d2=OLMo, d3=GPT-2~XL).
413	However, if the classifier exploited architecture fingerprints rather than depth signal, near-perfect accuracy would be expected since architecture perfectly determines depth label.
414	The observed 84.75\% with monotonically decreasing per-depth F1 (d0=0.98, d1=0.88, d2=0.76, d3=0.76) is more consistent with a depth-signal interpretation, as architecture fingerprinting would not produce this graded pattern.
415	We address this confound directly with a reverse-chain control below.
416	
417	\paragraph{Reverse-chain control.}
418	To empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\to$ OLMo $\to$ Pythia) reversing the model-depth assignment.
419	The reverse chain achieves 85.75\% (95\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\%, [81.0, 88.25]).
420	If the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.
421	
422	\paragraph{Cross-domain transfer.}
423	All prior experiments use WikiText-103 as the seed corpus.
424	To test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).
425	Five-fold cross-validation yields 74.1\% $\pm$ 2.0\% accuracy, compared to ${\sim}$78\% on the WikiText seed.
426	Per-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66---with d2 remaining the most challenging class.
427	The 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.
428	These results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.
429	
430	\subsection{Extended Discussion}
431	\label{app:extended_discussion}
432	
433	\paragraph{Depth-graduated curation.}
434	Current data curation operates on a binary human-vs-machine distinction \cite{dsir2023,qurating2024}.
435	Recursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.
436	The 70--85\% in-distribution accuracy and $\mathrm{EDD}_{0.75}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\S\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a pilot study (Appendix~\ref{app:curation_poc}) yields an inconclusive RF-vs-unfiltered comparison ($p>0.4$), though RF-filtered subsets significantly outperform size-matched random subsampling ($p<0.001$--$0.02$); large-scale validation remains open.
437	Importance weighting \cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.
438	
439	\paragraph{Toward a provenance toolkit.}
440	Depth estimation complements existing provenance methods along orthogonal axes.
441	Watermarking \cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.
442	Source attribution \cite{uchendu2020_attribution} identifies the generating model but not the generation history.
443	Depth estimation characterizes \emph{iterative reuse} regardless of generator cooperation or identity.
444	A layered provenance system combining these three signals---watermark presence, source model, and recursive generation depth---could support more nuanced data auditing than any single method.
445	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "50e80fb4-1edb-4c86-ab40-91f3e14a5334",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "b3e2cd41-ac31-49e7-a153-f424d9e257ce",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
      "content": "\\section{Additional Results}\n\\label{app:additional}\n\n\\subsection{Top-$k$ Feature Trajectories}\n\\label{app:topk_trajectories}\n\nFigure~\\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\\tau{=}0.9$) sampling.\nTop-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \\S\\ref{sec:atlas:strategy}.\nConcretely, the d0$\\to$d1 drop in \\textsc{p90\\_ppl} under top-$k$ is 78\\% (vs.\\ 87\\% for nucleus), and the d2$\\to$d3 reduction is 31\\% (vs.\\ 39\\% for nucleus).\nDespite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.\n\n\\subsection{Permutation Importance}\n\\label{app:permutation}\n\nTo verify that the Gini-based importance rankings in \\S\\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.\nThe top-2 features are stable across measures: \\textsc{p90\\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \\textsc{var\\_surprisal} in 8/9 (vs.\\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \\textsc{p75\\_ppl} displaces \\textsc{var\\_surprisal} to rank 3).\nKendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).\nPairwise Spearman correlations are: SHAP--Gini $\\rho{=}0.93$, SHAP--permutation $\\rho{=}0.84$, Gini--permutation $\\rho{=}0.76$.\nPer-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.\n\n\\subsection{Per-Class Recall}\n\\label{app:per_class}\n\nTable~\\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).\nDepth~0 recall exceeds 98\\% uniformly.\nAmong generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class recall (\\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}\n\\label{tab:per_class_recall}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & d0 & d1 & d2 & d3 \\\\\n\\midrule\nPythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\\\\nPythia, $\\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\\\\nPythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\\\\nOLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\\\\nOLMo, $\\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\\\\nOLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\\\\nGPT-2~XL, nuc.     & 99.2 & 85.9 & \\textbf{73.3} & 77.5 \\\\\nGPT-2~XL, $\\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\\\\nGPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{DCOL Iteration Details}\n\\label{app:dcol_iterations}\n\nTable~\\ref{tab:dcol_iterations} summarizes all six DCOL iterations.\nDeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\\%.}\n\\label{tab:dcol_iterations}\n\\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}\n\\toprule\nVer. & Backbone & Config & Outcome \\\\\n\\midrule\nv1 & DeBERTa & FT, m\\_lr $10^{-3}$ & Embed.\\ collapse (31.5\\%) \\\\\nv2 & DeBERTa & FT, m\\_lr $10^{-4}$ & OOM \\\\\nv3 & DeBERTa & FT, m\\_lr $10^{-4}$ & Forgetting + OOM \\\\\nv4 & DeBERTa & LoRA, m\\_lr $10^{-3}$ & Embed.\\ collapse \\\\\nv5 & DeBERTa & LoRA, m\\_lr $10^{-4}$ & NaN gradients \\\\\nv6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\\% ($-$13.7pp) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Zero-Shot LLM Prompt Template}\n\\label{app:zeroshot_prompt}\n\nBoth DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.\nThe system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).\nThe user message presents the passage (truncated to ${\\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.\nNo in-context examples are provided.\n\n\\begin{quote}\n\\small\n\\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\\ldots]''\n\n\\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \\{text\\}. Respond with ONLY a JSON object: \\{\\texttt{\"depth\"}: $\\langle$int 0--3$\\rangle$, \\texttt{\"confidence\"}: $\\langle$float 0--1$\\rangle$, \\texttt{\"reasoning\"}: $\\langle$str$\\rangle$\\}''\n\\end{quote}\n\n\\subsection{Temperature Robustness}\n\\label{app:multi_tau}\n\nThe cross-strategy results in \\S\\ref{sec:gen:crossstrategy} use a single temperature ($\\tau{=}0.9$).\nTo test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\\tau \\in \\{0.5, 0.7, 0.9, 1.1\\}$ on Pythia-1.4B.\n\n\\paragraph{Within-$\\tau$ robustness.}\nFor $\\tau \\in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\\% to 77.3\\% (Table~\\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.\nThe same top-5 features (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{mean\\_surprisal}, \\texttt{p75\\_ppl}) dominate across all $\\tau$ values with only minor rank-order variation.\n\n\\paragraph{Collapse at $\\tau{=}1.1$: memorization as prerequisite.}\nAt $\\tau{=}1.1$, 4-class accuracy drops to 57.2\\% and d1v2 AUC falls to 0.528.\nTraining loss reveals the mechanism: at low temperature ($\\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \\to 0.42 \\to 0.16$), indicating rapid memorization of the model's own output.\nAt $\\tau{=}1.1$, loss remains nearly flat ($2.27 \\to 1.91 \\to 1.85$)---high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.\nThis establishes \\emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.\n\n\\paragraph{Cross-$\\tau$ non-transferability.}\nLeave-one-$\\tau$-out transfer yields mean accuracy of 46.7\\% with mean d1v2 AUC of 0.319 (Table~\\ref{tab:multi_tau_cross})---worse than cross-strategy transfer (59.1\\%; \\S\\ref{sec:gen:crossstrategy}).\nHoldout $\\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.\nThis extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific, reinforcing the need for strategy-conditioned classifiers.\n\n\\paragraph{Ecological validity.}\nOn WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity---partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.\nOn noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Within-$\\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\\ depth $j$.}\n\\label{tab:multi_tau_within}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$\\tau$ & 4-class acc (\\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\\\\n\\midrule\n0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\\\\n0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\\\\n0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\\\\n1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-$\\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}\n\\label{tab:multi_tau_cross}\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nHoldout & Acc (\\%) & d1v2 AUC \\\\\n\\midrule\n$\\tau{=}0.5$ & 52.2 & 0.176 \\\\\n$\\tau{=}0.7$ & 41.0 & 0.299 \\\\\n$\\tau{=}0.9$ & 46.4 & 0.277 \\\\\n$\\tau{=}1.1$ & 47.1 & 0.525 \\\\\n\\midrule\nMean & 46.7 & 0.319 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Feature Overlap Analysis}\n\\label{app:feature_overlap}\n\nWe probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.\nPLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics---\\textsc{var\\_surprisal} and \\textsc{p90\\_ppl} yield negative $R^2$ under linear probing, indicating these features are not linearly accessible in the pretrained representation space.\nThis confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\\S\\ref{app:e2e}) stems from complementary---not redundant---representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.\n\n\\subsection{End-to-End Learning}\n\\label{app:e2e}\n\nDeBERTa-v3-base \\cite{he2021_deberta_v3} and RoBERTa-base \\cite{liu2019_roberta} finetuned end-to-end achieve 58.3\\% ($\\pm$4.7\\%) and 59.5\\% ($\\pm$3.2\\%) respectively---lagging the RF baseline (78.2\\%) by 19.9pp and 18.7pp.\nThe 1.2pp inter-backbone gap rules out architecture bias; Table~\\ref{tab:e2e_detail} shows both backbones share the same failure mode---high d0 F1 ($>$0.94) but collapsed d1/d2 performance (F1 $\\leq$ 0.42)---while RF achieves 0.596 d2 recall, a $>$2$\\times$ advantage at the hardest depth class.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class performance for end-to-end PLM classifiers vs.\\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}\n\\label{tab:e2e_detail}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nMethod & Acc (\\%) & d0 & d1 & d2 & d3 \\\\\n\\midrule\nDeBERTa-v3 & 58.3\\,$\\pm$\\,4.7 & .947 & .378 & .247 & .656 \\\\\nRoBERTa-base & 59.5\\,$\\pm$\\,3.2 & .958 & .416 & .261 & .647 \\\\\n\\midrule\nRF (19 feat.) & 78.2 & --- & --- & .596$^\\dagger$ & --- \\\\\n\\bottomrule\n\\multicolumn{6}{@{}l}{\\footnotesize $^\\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Feature space divergence.}\nSHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\\% of RF's total contribution.\nThree independent importance measures---SHAP, Gini, and permutation---show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \\S\\ref{app:permutation}), with \\texttt{p90\\_ppl} appearing in the SHAP top-2 in 9/9 cells and \\texttt{var\\_surprisal} in 8/9.\nLinear probing of PLM [CLS] representations yields negative $R^2$ for both \\texttt{var\\_surprisal} and \\texttt{p90\\_ppl} (\\S\\ref{app:feature_overlap}), indicating that pretrained representations lack the linear structure needed to recover perplexity tail statistics---a systematic representational gap rather than a backbone-specific artifact.\n\nDCOL \\cite{cloc2025} reached 64.5\\% (\\S\\ref{app:dcol_iterations}); all end-to-end approaches (58--65\\%) underperform feature-based methods, suggesting depth estimation benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.\nThis comparison is bounded by backbone scale ($\\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.\n\n\\subsection{Domain Bias Analysis}\n\\label{app:domain_bias}\n\nTo assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.\n\n\\paragraph{Methodological note.}\nAn initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\\%, seed-group prediction 20.8\\%).\nWe discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.\nThe results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.\n\n\\paragraph{Sub-A: Standard CV.}\nFive-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\\% to 82\\% across the 9 atlas cells (up to 2.5$\\times$ above the 33.3\\% chance level), confirming that depth signal is the dominant classification factor.\n\n\\paragraph{Sub-B: LOGO evaluation.}\nWe assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.\nLOGO mean accuracy is 72.1\\% (range 59.5--81.6\\%), matching standard CV (72.0\\%) within noise (before fix: 64.0\\%, reflecting the depth--group confound).\nPer-cell fold standard deviations range from 0.4pp to 1.4pp, indicating that cross-group generalization is as reliable as within-group classification.\n\n\\paragraph{Sub-C: Negative control.}\nWe train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\\%).\nDepth prediction accuracy averages 72.0\\%; seed-group prediction averages 10.2\\%---indistinguishable from chance (before fix: 20.8\\%, inflated by the depth--group confound).\nThe depth-to-seed-group accuracy ratio is 7.1$\\times$, confirming that the feature representation encodes depth but not seed-article identity.\n\nTaken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.\n\n\\subsection{Wild-Data Calibration}\n\\label{app:calibration}\n\nTable~\\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\\% Wilson CIs computed for C4 ($n{=}5{,}000$).}\n\\label{tab:calibration}\n\\begin{tabular}{@{}llrccc@{}}\n\\toprule\nModel & Source & $n$ & d0 (\\%) & FPR (\\%) & 95\\% Wilson CI \\\\\n\\midrule\nPythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\\\\n & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\\\\n\\addlinespace\nGPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\\\\n & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\\\\n\\addlinespace\nOLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\\\\n & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOn WikiText-103, all three classifiers achieve $\\geq$98.5\\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.\nOn C4, FPR varies sharply: OLMo (4.7\\%) vs.\\ Pythia (20.2\\%) and GPT-2~XL (22.4\\%).\nC4 misclassifications concentrate in template and SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0 passages), rather than in random noise.\nThe model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.\nAmong C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\\%), d2 (3.7\\%), d3 (9.6\\%); for OLMo, d1 (2.9\\%), d2 (0.5\\%), d3 (1.3\\%)---the non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.\n\n\\subsection{Downstream Curation PoC}\n\\label{app:curation_poc}\n\nTo validate that depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.\nWe fine-tune Pythia-410M with LoRA ($r{=}16$, $\\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.\nConditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\\approx$25\\%, moderate $\\approx$50\\%, soft threshold).\nTable~\\ref{tab:curation_poc} reports per-condition perplexity; Table~\\ref{tab:curation_comparisons} reports pairwise contrasts.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\\,: $p<0.05$ (paired $t$-test vs.\\ unfiltered).}\n\\label{tab:curation_poc}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\nCondition & Mean PPL & Std & $n$ & $\\Delta$ vs Unfilt. & $p$ & $d_z$ \\\\\n\\midrule\nunfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\\\\nrf\\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\\\\nrf\\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\\\\nrf\\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\\\\noracle\\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\\\\noracle\\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\\\\nrandom\\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\\\\nrandom\\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\\\\nrandom\\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\\,: $p<0.05$; $^{**}$\\,: $p<0.01$.}\n\\label{tab:curation_comparisons}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nComparison & $\\Delta$ PPL & $t$ & $p$ \\\\\n\\midrule\nrf\\_strict vs random\\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\\\\nrf\\_moderate vs random\\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\\\\nrf\\_soft vs random\\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\\\\nrf\\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Reference Model Ablation}\n\\label{app:ref_ablation}\n\n\\begin{table}[h]\n\\centering\n\\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}\n\\label{tab:ref_ablation}\n\\begin{tabular}{lcc}\n\\toprule\nReference Model & Architecture & Accuracy (\\%) \\\\\n\\midrule\nPythia-1.4B (self) & GPT-NeoX & 78.6 $\\pm$ 0.6 \\\\\nOLMo-1B (cross) & OLMo & 74.5 $\\pm$ 0.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Cross-Scale Full Results}\n\\label{app:cross_scale_full}\n\nThis section provides the full cross-scale analysis summarized in \\S\\ref{sec:gen:crossscale}.\nWe extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \\in \\{0, 1, \\ldots, 5\\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).\nFeature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.\n\n\\paragraph{Scale comparison.}\nTable~\\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-scale comparison: 4-class RF accuracy (\\%, depths 0--3, nucleus), $\\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\\% bootstrap. Chance = 25\\%.}\n\\label{tab:cross_scale}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nModel & 4-class acc & $\\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\\\\n\\midrule\nGPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\\\\nOLMo-1B & 78.8 & 4 & 0.997 \\\\\nPythia-1.4B & 78.2 & 4 & 0.998 \\\\\n\\midrule\nLlama-3.1-8B & 70.2\\,[68.3, 72.4] & 4 & 0.949 \\\\\nQwen2.5-7B & 60.1\\,[58.0, 62.1] & ${>}5$ & 0.969 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{(1) Depth signal persists at 7--8B scale.}\nBoth 7--8B models substantially exceed the 25\\% chance baseline: Llama-3.1-8B achieves 70.2\\% (95\\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\\% ($[58.0, 62.1]$), confirming that recursive depth remains estimable from perplexity-based features even when the generator is 5--7$\\times$ larger than the reference model.\nDepth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).\n\n\\paragraph{(2) EDD at 7--8B scale.}\nAt threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\\ref{tab:cross_scale_auc}), yielding $\\mathrm{EDD}_{T{=}0.70} > 5$---exceeding the $\\mathrm{EDD}{=}4$ observed at 1--1.5B.\nLlama-3.1-8B matches the smaller models at $\\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.\nBoth larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\\ 0.852 at 1--1.5B).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Consecutive binary AUC for 7--8B models (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a non-monotonic (U-shaped) pattern with all pairs above $T$.}\n\\label{tab:cross_scale_auc}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nModel & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\\\\n\\midrule\nLlama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\\\\nQwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{(3) Divergent AUC trajectories and instruction-tuning effect.}\nAmong instruction-tuned models, Llama-3.1-8B exhibits monotonic AUC decay consistent with the 1--1.5B pattern, while Qwen2.5-7B shows a U-shaped recovery beyond d2v3 (Table~\\ref{tab:cross_scale_auc}).\nA base-model control (Llama-3.1-8B without instruction tuning) clarifies the causal direction: the base model achieves 59.9\\% four-class accuracy (95\\% CI [57.8, 62.15], $\\mathrm{EDD}_{0.70}{=}2$) with non-monotonic AUC decay (Table~\\ref{tab:llama3_base_auc}), while the instruction-tuned variant reaches 70.2\\% with strictly monotonic decay.\nThe base-model control experiment suggests instruction-tuning regularizes rather than confounds the depth signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise AUC: Llama-3.1-8B Base vs.\\ Instruct.}\n\\label{tab:llama3_base_auc}\n\\begin{tabular}{lccccc}\n\\toprule\nVariant & $d_{0\\text{v}1}$ & $d_{1\\text{v}2}$ & $d_{2\\text{v}3}$ & $d_{3\\text{v}4}$ & $d_{4\\text{v}5}$ \\\\\n\\midrule\nBase & 0.918 & 0.794 & 0.682 & 0.730 & 0.595 \\\\\nInstruct & 0.965 & 0.874 & 0.771 & 0.716 & 0.618 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe base model exhibits non-monotonic decay with a U-shaped recovery at $d_{3\\text{v}4}$, while the instruction-tuned variant shows strictly monotonic decay. Both variants exceed chance (AUC $> 0.5$) at all boundaries, confirming depth signal exists regardless of instruction-tuning, though instruction-tuning strengthens and regularizes it.\n\n\\paragraph{Caveats.}\nFor Qwen2.5-7B, the CI lower bound (58.0\\%) does not exclude sub-60\\% accuracy; Llama-3.1-8B's lower bound (68.3\\%) is more comfortably above chance but still below the 75--83\\% range at 1--1.5B.\nThe divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.\n\n\\paragraph{Confounds.}\n\\label{app:cross_scale_confounds}\nFour confounds limit these results: (1)~4-bit NF4 QLoRA quantization (absent at 1--1.5B) may distort the perplexity distribution independently of depth; (2)~smaller sample size (500 vs.\\ 5{,}000 per depth) widens confidence intervals; (3)~evaluation is limited to nucleus sampling, leaving other strategies untested at this scale; (4)~vocabulary mismatch between 7--8B generators and the 1.4B reference model.\nThe base-model control partially addresses a former confound (instruction-tuning): since the base variant shows weaker signal with non-monotonic decay while the instruction-tuned variant shows stronger monotonic signal, instruction-tuning regularizes rather than confounds depth estimation.\nThe remaining confounds are not mutually independent---quantization and vocabulary mismatch both affect the perplexity distribution---making it infeasible to attribute the observed accuracy gap (60--70\\% vs.\\ 78--85\\% at 1--1.5B) to any single factor.\n\n\\subsection{Cross-Boundary Generalization}\n\\label{app:cross_boundary}\n\nThe preceding experiments assume a single model family generates all recursive depths.\nIn practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.\nWe probe whether the depth signal persists under two relaxations of the single-model assumption.\n\n\\paragraph{Cross-model recursive chains.}\nWe construct a heterogeneous chain: human text (d0) $\\to$ Pythia-1.4B generates d1 $\\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.\nEach recursive step uses a \\emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.\nA 4-class Random Forest achieves 84.75\\% accuracy (95\\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).\nPairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.\nThese results suggest that distributional artifacts of recursive generation persist across model boundaries---providing preliminary evidence consistent with a process-level depth signal rather than individual generator artifacts.\n\n\\paragraph{Confound discussion.}\nThe heterogeneous chain confounds architecture identity with depth (d1=Pythia, d2=OLMo, d3=GPT-2~XL).\nHowever, if the classifier exploited architecture fingerprints rather than depth signal, near-perfect accuracy would be expected since architecture perfectly determines depth label.\nThe observed 84.75\\% with monotonically decreasing per-depth F1 (d0=0.98, d1=0.88, d2=0.76, d3=0.76) is more consistent with a depth-signal interpretation, as architecture fingerprinting would not produce this graded pattern.\nWe address this confound directly with a reverse-chain control below.\n\n\\paragraph{Reverse-chain control.}\nTo empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\\to$ OLMo $\\to$ Pythia) reversing the model-depth assignment.\nThe reverse chain achieves 85.75\\% (95\\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\\%, [81.0, 88.25]).\nIf the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.\n\n\\paragraph{Cross-domain transfer.}\nAll prior experiments use WikiText-103 as the seed corpus.\nTo test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).\nFive-fold cross-validation yields 74.1\\% $\\pm$ 2.0\\% accuracy, compared to ${\\sim}$78\\% on the WikiText seed.\nPer-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66---with d2 remaining the most challenging class.\nThe 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.\nThese results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.\n\n\\subsection{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Depth-graduated curation.}\nCurrent data curation operates on a binary human-vs-machine distinction \\cite{dsir2023,qurating2024}.\nRecursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.\nThe 70--85\\% in-distribution accuracy and $\\mathrm{EDD}_{0.75}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a pilot study (Appendix~\\ref{app:curation_poc}) yields an inconclusive RF-vs-unfiltered comparison ($p>0.4$), though RF-filtered subsets significantly outperform size-matched random subsampling ($p<0.001$--$0.02$); large-scale validation remains open.\nImportance weighting \\cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.\n\n\\paragraph{Toward a provenance toolkit.}\nDepth estimation complements existing provenance methods along orthogonal axes.\nWatermarking \\cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.\nSource attribution \\cite{uchendu2020_attribution} identifies the generating model but not the generation history.\nDepth estimation characterizes \\emph{iterative reuse} regardless of generator cooperation or identity.\nA layered provenance system combining these three signals---watermark presence, source model, and recursive generation depth---could support more nuanced data auditing than any single method.\n",
      "numLines": 445,
      "startLine": 1,
      "totalLines": 445
    }
  },
  "sourceToolAssistantUUID": "50e80fb4-1edb-4c86-ab40-91f3e14a5334",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 57_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "b3e2cd41-ac31-49e7-a153-f424d9e257ce",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 58_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Assistant

_source line 59 · 2026-05-16T19:33:02.350Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have enough to evaluate all the issues. Let me also check for the specific "universal" uses and missing references. Let me do a quick grep.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b3e2cd41-ac31-49e7-a153-f424d9e257ce",
  "isSidechain": false,
  "requestId": "req_011Cb6ohaeYL1bZLT7pZCQ7A",
  "type": "assistant",
  "uuid": "5be85046-86a2-43b5-91cc-6f78e45eb0b6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015G6AAfB6gFQ3fR7QHW3HwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14159,
      "cache_read_input_tokens": 55626,
      "output_tokens": 303,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14159,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 303,
          "cache_read_input_tokens": 55626,
          "cache_creation_input_tokens": 14159,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14159
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

_source line 60 · 2026-05-16T19:33:04.693Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01NyBvtMqgZLFHpu8fGZdLNY`</summary>

```json
{
  "pattern": "universal|Universal",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5be85046-86a2-43b5-91cc-6f78e45eb0b6",
  "isSidechain": false,
  "requestId": "req_011Cb6ohaeYL1bZLT7pZCQ7A",
  "type": "assistant",
  "uuid": "0a22c6ad-dee2-49ae-89f7-0e862a943a53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015G6AAfB6gFQ3fR7QHW3HwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14159,
      "cache_read_input_tokens": 55626,
      "output_tokens": 303,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14159,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 303,
          "cache_read_input_tokens": 55626,
          "cache_creation_input_tokens": 14159,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14159
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

_source line 61 · 2026-05-16T19:33:04.720Z_

<details><summary>↩ Tool result · `toolu_01NyBvtMqgZLFHpu8fGZdLNY`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:99:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex:110:Cross-model recursive chains (84.75\%), validated by a reverse-chain control (85.75\%; Appendix~\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\%) further confirm signal universality.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex:14:Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \textbf{universal and scale-variant} across the three model families and three decoding strategies studied.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:494:\@writefile{toc}{\contentsline {subsection}{\numberline {4.2}Feature Universality}{5}{subsection.4.2}\protected@file@percent }
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:495:\newlabel{sec:atlas:features}{{4.2}{5}{Feature Universality}{subsection.4.2}{}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0a22c6ad-dee2-49ae-89f7-0e862a943a53",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "260c138c-efe0-4144-a12b-53d4c3cfbd67",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:99:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex:110:Cross-model recursive chains (84.75\\%), validated by a reverse-chain control (85.75\\%; Appendix~\\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\\%) further confirm signal universality.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex:14:Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \\textbf{universal and scale-variant} across the three model families and three decoding strategies studied.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:494:\\@writefile{toc}{\\contentsline {subsection}{\\numberline {4.2}Feature Universality}{5}{subsection.4.2}\\protected@file@percent }\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:495:\\newlabel{sec:atlas:features}{{4.2}{5}{Feature Universality}{subsection.4.2}{}}",
    "numLines": 5
  },
  "sourceToolAssistantUUID": "0a22c6ad-dee2-49ae-89f7-0e862a943a53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 62 · 2026-05-16T19:33:05.981Z_

<details><summary>↩ Tool result · `toolu_014SbuQWXuQ28xue2FHptWCq`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.bbl:119:\bibitem[{Gerstgrasser et~al.(2024)Gerstgrasser, Schaeffer, Dey, Rafailov,
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.bbl:122:Matthias Gerstgrasser, Rylan Schaeffer, Apratim Dey, Rafael Rafailov, Henry
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib:52:  author    = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:908:\bibcite{gerstgrasser2024_accumulate}{{15}{2024}{{Gerstgrasser et~al.}}{{Gerstgrasser, Schaeffer, Dey, Rafailov, Sleight, Hughes, Korbak, Agrawal, Pai, Gromov, Roberts, Yang, Donoho, and Koyejo}}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4ea470da-f00f-4cde-8192-9924b1041650",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "4e823a46-b39b-4d87-ad9a-89ecd58f4898",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.bbl:119:\\bibitem[{Gerstgrasser et~al.(2024)Gerstgrasser, Schaeffer, Dey, Rafailov,\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.bbl:122:Matthias Gerstgrasser, Rylan Schaeffer, Apratim Dey, Rafael Rafailov, Henry\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib:52:  author    = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:908:\\bibcite{gerstgrasser2024_accumulate}{{15}{2024}{{Gerstgrasser et~al.}}{{Gerstgrasser, Schaeffer, Dey, Rafailov, Sleight, Hughes, Korbak, Agrawal, Pai, Gromov, Roberts, Yang, Donoho, and Koyejo}}}",
    "numLines": 4
  },
  "sourceToolAssistantUUID": "4ea470da-f00f-4cde-8192-9924b1041650",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 63 · 2026-05-16T19:33:05.958Z_

<details open><summary>🔧 Tool call — Grep · `toolu_014SbuQWXuQ28xue2FHptWCq`</summary>

```json
{
  "pattern": "Schaeffer|Frank.*Hall|Rennie.*Srebro|frank_hall|rennie_srebro|schaeffer2025",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "260c138c-efe0-4144-a12b-53d4c3cfbd67",
  "isSidechain": false,
  "requestId": "req_011Cb6ohaeYL1bZLT7pZCQ7A",
  "type": "assistant",
  "uuid": "4ea470da-f00f-4cde-8192-9924b1041650",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015G6AAfB6gFQ3fR7QHW3HwW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14159,
      "cache_read_input_tokens": 55626,
      "output_tokens": 303,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14159,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 303,
          "cache_read_input_tokens": 55626,
          "cache_creation_input_tokens": 14159,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14159
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

_source line 64 · 2026-05-16T19:34:09.959Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me also check the abstract for number density and for explicit d0-excluded metrics. Let me also look at the subsection heading "Feature Universality" which is the compiled output's heading for \S4.2 (which in the source is "Feature Consistency Across the Grid").

Let me now check a few more things:
1. The EDD footnote mentions "universal quantifier" which is a mathematical term, not a claim about the method
2. introduction.tex line 14 still uses "universal and scale-variant" - though it's immediately qualified with "across the three model families and three decoding strategies studied"
3. generalization.tex line 110 says "signal universality" without qualification


4. There's a mismatch between the compiled .aux file showing "Feature Universality" and the source atlas.tex line 44 which has "Feature Consistency Across the Grid" - I need to verify which one is actually in the current source.

Looking at the .aux file entries, they reference "Feature Universality" but the source file shows the heading was changed to "Feature Consistency Across the Grid", so the .aux file is stale from a previous compilation.

Now checking the curation PoC treatment: it's correctly absent from the contribution list, and in the appendix discussion it's properly framed as inconclusive with the RF-filtered results showing statistical significance compared to random subsampling, while noting that large-scale validation is still needed.

However, in discussion.tex the curation PoC is presented as an application direction with just a parenthetical appendix reference, which seems to downplay its inconclusive status. I should verify whether this framing aligns with the reviewer feedback about removing or downgrading it.

For the theory connection, I'm seeing the model-collapse dynamics cited in atlas.tex where early recursion narrows the surprisal distribution while later steps affect the perplexity tail, and this connects to the EDD definition in the method section.

Now looking at the novelty claim against Dohmatob 2024: the introduction and related work do state the distinction—they characterize degradation assuming depth is known, while we estimate depth from text alone—but I'm not seeing a clear articulation of how our work specifically validates or extends Dohmatob's tail erosion predictions rather than just applying them.

For the citation metadata, the DeBERTa key has a cosmetic mismatch (2021 in the key but 2023 in the year field), though the actual publication year is correct. The Alemohammad citation appears to have author names that need verification. I'm counting through all the numerical values mentioned in the abstract—there are quite a few metrics and percentages scattered throughout, ranging from the dataset size and model configurations down to specific performance results and statistical measures.

Now I'm checking whether the "universal" language issue was actually addressed in the revisions. The introduction still uses the word "universal" despite the qualifier about the three model families and strategies, and there's another instance in the generalization section referring to "signal universality." The subsection heading was improved from "Feature Universality" to "Feature Consistency Across the Grid," which helps, but the core overclaim persists.

For the d0 inflation concern, that looks resolved—the abstract now presents the 66.4% figure alongside the d1–d3 results showing 55.4% and the 1.7× chance comparison, so the context is clearer.

The curation proof-of-concept was partially fixed by removing it from the main contributions and labeling it as inconclusive in the extended discussion, though the main discussion section still presents it as a potential application without that same caveat.

The theory connection attempt links feature hierarchy shifts to model collapse, but it's still missing a formal analysis that would tie this back to Dohmatob's tail scaling predictions.

For the novelty question against Dohmatob's 2024 work, the related work section now clarifies that previous work assumes depth is known while this addresses the inverse problem, but it doesn't quite make the explicit connection that Dohmatob predicted tail erosion and this work operationalizes that prediction as measurable classification features.

The missing references issue remains unresolved—Schaeffer et al. (2025), Frank & Hall (2001), and Rennie & Srebro (2005) still aren't cited anywhere.

There are also persistent citation metadata problems: the alemohammad2024_mad entry still has incorrect author names that need fixing, and the abstract is still packed with over 20 numbers when it should be more selective.

I should also check whether the novelty positioning, contribution framing, and related work coverage are truly complete, and scan for any remaining writing quality or format issues. The novelty hinges on operationalizing collapse theory through the EDD metric, though the paper doesn't make it explicit that this is the theoretical contribution—and using perplexity tail statistics for classification feels somewhat incremental once you're aware of tail erosion from prior work. I'm also noticing some significant gaps in the related work: Schaeffer et al. (2025) directly challenges whether model collapse actually occurs in practice, which could undermine the whole premise, and the ordinal classification literature (Frank & Hall, Rennie & Srebro) is barely covered despite being relevant to the task formulation. I should scan for other recent work before drafting the review.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4e823a46-b39b-4d87-ad9a-89ecd58f4898",
  "isSidechain": false,
  "requestId": "req_011Cb6oiEJD7gw6TnHweS5ie",
  "type": "assistant",
  "uuid": "a9d1bdf1-db9d-4c76-bcf7-bdd3a256a891",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W8HRg9AGWMDoHEjmT8VLb5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1193,
      "cache_read_input_tokens": 69785,
      "output_tokens": 6974,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1193,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6974,
          "cache_read_input_tokens": 69785,
          "cache_creation_input_tokens": 1193,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1193
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

_source line 65 · 2026-05-16T19:34:09.961Z_

Now I have all the information needed. Let me compile my review and post to the Director.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a9d1bdf1-db9d-4c76-bcf7-bdd3a256a891",
  "isSidechain": false,
  "requestId": "req_011Cb6oiEJD7gw6TnHweS5ie",
  "type": "assistant",
  "uuid": "9a8ba64d-e59d-4200-9822-682f613a1054",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W8HRg9AGWMDoHEjmT8VLb5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1193,
      "cache_read_input_tokens": 69785,
      "output_tokens": 6974,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1193,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6974,
          "cache_read_input_tokens": 69785,
          "cache_creation_input_tokens": 1193,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1193
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

_source line 66 · 2026-05-16T19:35:42.971Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01PtkooXinLZaQc4DfaS6kSz`</summary>

```json
{
  "text": "## Round 6 Review — Reviewer 2（新颖性 + Related Work + 写作完整性）\n\n---\n\n## 遗留问题评估\n\n### 1. R3-N4 'Universal' overclaim\n**[PARTIALLY ADDRESSED]**\n\nIntroduction (line 14) 现在写 \"**universal and scale-variant** across the three model families and three decoding strategies studied\"——\"universal\" 仍在，但紧跟范围限定语。Atlas 小节标题已从 \"Feature Universality\" 改为 \"Feature Consistency Across the Grid\"（source: atlas.tex §4.2）。\n\n**但 generalization.tex line 110 仍有未限定的 \"signal universality\"：**\n> \"Cross-model recursive chains (84.75%), validated by a reverse-chain control (85.75%; Appendix), and cross-domain transfer (arXiv 74.1%) further confirm signal universality.\"\n\n此处无范围限定词。Introduction 的用法可接受（有紧邻限定），但 generalization.tex 的 \"signal universality\" 和 Introduction 的 \"universal\" 仍然构成 overclaim 风险。建议替换为 \"signal consistency across all tested configurations\" 或类似表述。\n\n---\n\n### 2. R1-W2 d0 inflation\n**[RESOLVED]**\n\nAbstract (line 7) 明确标注：\n> \"Cross-model transfer reaches 66.4% (d1–d3 balanced accuracy: 55.4%, 1.7× chance)\"\n\nCross-model table caption 也注明 \"d1–d3 bal. acc\"。Limitations §明确讨论 d0 inflation。充分解决。\n\n---\n\n### 3. R4-W1 Curation PoC non-significant\n**[PARTIALLY ADDRESSED]**\n\n正面：\n- **已从 contribution list 删除**（Introduction 三个 bullet 无 curation）\n- Appendix extended discussion (line 436) 明确写 \"inconclusive RF-vs-unfiltered comparison (p>0.4)\"\n\n残留问题：\n- Discussion.tex (line 7) 仍以应用方向口吻提及 \"depth-graduated data curation—retaining d1 while filtering d3+—complementing binary detection\" 并引向 Appendix，但**未在正文 discussion 中标注 inconclusive**。读者可能只读正文不读 appendix，会误认为这是已验证的应用。\n- 建议：discussion.tex 中加 \"(preliminary; pilot results inconclusive, Appendix X)\" 或类似限定语。\n\n---\n\n### 4. R4-W3 方法论新颖性 + 理论分析\n**[PARTIALLY ADDRESSED]**\n\nAtlas.tex (§4.2, lines 60-62) 提供了定性连接：\n> \"This transition aligns with model-collapse dynamics: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).\"\n\n但这是 post-hoc 对齐式叙述，**不是理论分析**。论文未提供：\n- 从 Dohmatob (2024) 尾部缩放律推导出 feature 设计的形式化 motivation\n- 理论预测 EDD 应随模型规模/decoding 如何变化的 bound\n- 任何 proposition/theorem 连接 collapse theory → discriminability\n\n对 EMNLP 论文来说这不一定是 must-fix，但它确实限制了 excitement 评分——当前 contribution 本质上是 \"empirical pipeline + systematic evaluation\"，理论深度有限。\n\n---\n\n### 5. R5-N1 Novelty vs Dohmatob (2024) tail prediction\n**[PARTIALLY ADDRESSED]**\n\nRelated Work (§2, line 7) 写：\n> \"These works characterize degradation but assume depth is known a priori; we address the inverse problem of estimating depth from text alone.\"\n\n这句建立了任务层面的区分。但**具体到 perplexity tail statistics 的使用**，论文没有明确说：\n\n\"Dohmatob et al. (2024) predict theoretically that distributional tails erode under recursive generation; however, they do not demonstrate that this prediction can be operationalized as a depth classifier feature, nor do they address the inverse estimation problem. Our contribution is to show that tail statistics are not only a theoretical consequence of collapse but a practically sufficient and dominant signal for ordinal depth classification.\"\n\n这种精确区分缺失使得 reviewer 可能认为本文只是\"把已知理论预测直接变成 feature\"——降低 novelty 感知。\n\n建议：在 Introduction 或 Related Work 中加 2-3 句明确 bridge from theory-prediction → practical operationalization。\n\n---\n\n### 6. R5-W4 Related Work 遗漏\n**[NOT ADDRESSED]**\n\n三篇指定参考文献均未出现在 references.bib 或正文中：\n\n1. **Schaeffer et al. (2025) \"Model Collapse Does Not Mean What You Think\"** — 直接挑战 model collapse 的普遍性假设，对本文前提有重要影响。如果 collapse 在实际 accumulative training 中不显著发生（Schaeffer 的论点），本文方法的适用范围需要讨论。\n2. **Frank & Hall (2001)** — 经典 ordinal classification 方法（pairwise decomposition），是 CORAL 等方法的先驱，Ordinal Classification 段落应引用。\n3. **Rennie & Srebro (2005)** — ordinal regression 的 loss function 基础工作。\n\n当前 Ordinal Classification 段落（related_work.tex lines 19-21）只引用了 CORAL (2020) 和 CLOC (2025)，缺乏该领域的经典奠基工作。\n\n---\n\n### 7. R3-M1 引用元数据\n**[PARTIALLY ADDRESSED]**\n\n- `he2021_deberta_v3`：key 名含 \"2021\" 但 year=2023（ICLR 2023 发表），渲染结果正确。**已解决**（cosmetic key 名不影响读者）。\n\n- `alemohammad2024_mad`：**作者仍然错误。** 当前 bib 列 \"Romero, Oscar\" 和 \"Ramanarayanan, Sriram\"，实际作者应为 **\"Leong, Oscar\"** 和 **\"Rangamani, Akshay\"**（arXiv:2307.01850 确认）。这是会被 reviewer/camera-ready 审查发现的硬错误。\n\n---\n\n### 8. R4-W5 Abstract 信息密度\n**[NOT ADDRESSED]**\n\n当前 abstract 包含 **20+ 个独立数字**（我逐条计数）：180K, 3, 3, 4, 19, 70-85%, 25%, 9/9, 8/9, EDD₀.₇₅=4, p=0.001, §4.4, 66.4%, 55.4%, 1.7×, 84.75%, 85.75%, 70.2%, EDD=4, 60.1%, 59.9%, 70.2%, 98.5%。\n\n这远超 EMNLP 论文 abstract 的典型密度（通常 5-8 个关键数字）。信息过载导致：\n- 核心 message 被稀释——读者无法在一次阅读中抓住 \"what's the main result\"\n- 与低层 detail 混杂（如具体 p-value、section 引用不属于 abstract）\n- \"§4.4\" 引用不应出现在 abstract 中\n\n建议将 abstract 精简到核心 message + 3-5 个关键数字，将 secondary results 移入 introduction。\n\n---\n\n## 新发现\n\n### N1 [warning] Contribution bullet 3 过度压缩\nIntroduction contribution list 第三个 bullet 在一个列表项中堆叠了 **7 个 generalization axes + 6 个数字 + 1 个 ablation result**：\n\n> \"Cross-model recursive chains (84.75%), cross-scale observations on two 7B models (70.2% and 60.1%), cross-domain transfer (arXiv 74.1%), temperature robustness (τ∈[0.5,0.9]), and reference model independence (Δ=4pp). A surface-text ablation (zero-shot LLMs at 30–36%, 42pp below RF; §5.1)...\"\n\n这使 contribution framing 不清晰——reader 无法判断哪些是 main contributions vs supporting evidence。建议将 \"seven axes of generalization\" 作为一句概括，核心数字挑 2-3 个最重要的。\n\n### N2 [minor] \"consistent across all three families\" 的统计支撑不均\nIntroduction (line 14) 和 abstract 都说 \"consistent across all three model families\"，但 EDD bootstrap 测试显示：\n- Pythia: p=0.001 (significant)\n- OLMo: p=0.091 (marginal)\n- GPT-2 XL: p=0.505 (non-significant)\n\n论文在 §4.4 正确报告了 \"graded statistical support\"，但 abstract/introduction 的 framing 没有反映这种梯度。这不是 factual error（方向一致确实是 \"consistent\"），但 framing 上偏乐观。\n\n### N3 [minor] Discussion 缺失对 Schaeffer 反论点的讨论\n如果 model collapse 在 accumulative training 中不必然发生（Schaeffer et al. 2025 的论点），本文方法的实际应用场景会受限。Discussion/Limitations 应承认这种可能性并讨论 method 在 accumulative（非 purely recursive）设置下的适用性。\n\n---\n\n## Strengths（本版本）\n\n1. **任务定义清晰且有价值**：将 recursive depth estimation 形式化为 ordinal classification 是该领域的自然但此前未被提出的 framing，EDD 指标设计合理。\n2. **实验系统性优秀**：3×3 atlas + 7 轴 generalization + ablation + controls 的实验矩阵远超 typical EMNLP 论文的thoroughness。\n3. **d0 inflation 的诚实处理**：Limitations 和 abstract 都直面 d0 inflation，d1-d3 balanced accuracy 明确报告。\n4. **Domain bias 分析严谨**：发现 bug → 修复 → 报告 both versions 的做法值得肯定。\n5. **Cross-boundary chain + reverse control**：双向链实验有效 address architecture confound，设计巧妙。\n\n---\n\n## Weaknesses\n\n### Must-Fix\n**MF1** [critical] `alemohammad2024_mad` 作者错误（\"Romero, Oscar\" → \"Leong, Oscar\"，\"Ramanarayanan, Sriram\" → \"Rangamani, Akshay\"）。这是引用诚信问题，必须修正。\n\n**MF2** [critical] Related Work 遗漏 Schaeffer et al. (2025)。该工作直接质疑 model collapse 的普遍性前提——不引用不讨论构成对 literature 的选择性呈现。\n\n### Should-Fix\n**SF1** Abstract 数字过载（20+ 数字，含不应在 abstract 中出现的 \"§4.4\"）。精简至核心 message + 5-8 个关键结果。\n\n**SF2** \"universal/universality\" 仍存在于 introduction 和 generalization.tex，应统一替换为 \"consistent across all tested configurations\" 或类似。\n\n**SF3** Discussion 正文 curation 提及未标注 inconclusive，与 appendix 描述不一致。\n\n**SF4** Novelty vs Dohmatob (2024) 的区分不够 explicit——需要 2-3 句明确说 \"tail erosion is a theoretical prediction; our contribution is demonstrating it as a sufficient and dominant practical depth signal\"。\n\n**SF5** Ordinal Classification 段落缺乏经典工作（Frank & Hall 2001, Rennie & Srebro 2005），两篇引用不足以支撑 \"we situate our work in this field\" 的定位。\n\n### Minor\n- Contribution bullet 3 信息密度过高，建议拆分或概括\n- Abstract 中的 \"§4.4\" 引用不符合 abstract 写作规范\n- Introduction \"universal and scale-variant\" 用词矛盾（universal 意味着跨 scale 通用，scale-variant 意味着 scale 依赖），建议改为 \"consistent in direction but scale-dependent in magnitude\"\n\n---\n\n## Missing References\n\n1. **Schaeffer, R., Balestriero, R., & LeCun, Y. (2025).** \"Model Collapse Does Not Mean What You Think.\" — 直接质疑 collapse 普遍性\n2. **Frank, E. & Hall, M. (2001).** \"A Simple Approach to Ordinal Classification.\" — 经典 pairwise ordinal decomposition\n3. **Rennie, J. & Srebro, N. (2005).** \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels.\" — ordinal loss functions\n\n---\n\n## Questions for Authors\n\n1. 如果 Schaeffer et al. (2025) 的论点成立（accumulative training 不导致 collapse），你们的方法在 realistic web-scale 训练中（非 purely recursive）的适用性如何？是否需要一个 non-recursive contamination 的 negative result 来 bound 方法的适用范围？\n\n2. Abstract 中 \"consistent across all three families\" 的 statistical support 是 p=0.001/0.091/0.505——你们认为在什么 p-value 阈值下不再适合用 \"consistent\" 描述？\n\n3. 是否考虑过从 Dohmatob (2024) 的尾部缩放律 formally derive EDD 的理论下界？这可能从根本上提升 novelty 定位。\n\n---\n\n## Overall Assessment\n\n**Soundness**: 3.5/5 — 实验设计严谨、controls 充分，但引用错误（alemohammad）和遗漏（Schaeffer）构成 scholarly rigor 瑕疵。\n\n**Excitement**: 3/5 — 新任务定义有价值，但核心方法（perplexity tail → RF classifier）在知道 Dohmatob (2024) 后 conceptually straightforward，且缺乏理论深度。若 Introduction/Related Work 更好地 frame \"inverse problem\" 的非平凡性，excitement 可能提升。\n\n**Reproducibility**: 4.5/5 — 19 features 明确定义，所有超参数报告完整，code release promised。\n\n**Overall**: 3/5 (Findings-level) — 系统性实验和新任务定义够 Findings 水平；要进 Main Conference 需要 (a) 补齐 Related Work + 明确 novelty differentiation from Dohmatob, (b) 修正 abstract/framing 过度压缩问题, (c) 理想情况下加入理论贡献。\n\n**一句话总结**：实验功底扎实、task formalization 有意义，但 novelty framing 不清晰（vs Dohmatob 2024 的直接预测）、Related Work 有显著遗漏、abstract 信息过载，当前更适合 Findings 而非 Main Conference。",
  "reviewer_id": "2",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9a8ba64d-e59d-4200-9822-682f613a1054",
  "isSidechain": false,
  "requestId": "req_011Cb6oiEJD7gw6TnHweS5ie",
  "type": "assistant",
  "uuid": "cedaa4a7-60db-4a92-921f-861623e69cdc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W8HRg9AGWMDoHEjmT8VLb5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1193,
      "cache_read_input_tokens": 69785,
      "output_tokens": 6974,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1193,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6974,
          "cache_read_input_tokens": 69785,
          "cache_creation_input_tokens": 1193,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1193
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

_source line 67_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## Round 6 审稿任务 — Reviewer 2（新颖性 + Related Work + 写作完整性）  ### Venue 信息 - **目标**: EMNLP 2026 Main Conference (ARR May cycle) - **Deadline**: 2026-05-25 - **格式**: ACL 模板，8 页正文 + 无限参考文献，d…",
  "leafUuid": "cedaa4a7-60db-4a92-921f-861623e69cdc",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 68_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Tool result

_source line 69 · 2026-05-16T19:35:47.138Z_

<details><summary>↩ Tool result · `toolu_01PtkooXinLZaQc4DfaS6kSz`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cedaa4a7-60db-4a92-921f-861623e69cdc",
  "isSidechain": false,
  "promptId": "d7ad551a-ffcb-473c-8d9f-ff38534406a8",
  "type": "user",
  "uuid": "3cdf7fae-a851-4c77-8c9c-aa06dc0aa07b",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "cedaa4a7-60db-4a92-921f-861623e69cdc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 70_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 71 · 2026-05-16T19:41:19.818Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-16T19:41:19.818Z",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "content": "[Round 6 审稿请求]:\n## 交叉分享 — Reviewer 1 的完整审稿意见\n\n请逐条回应以下 Reviewer 1 的审稿意见。对每个观点用 **[AGREE]** 或 **[REBUT]** 标记，并提供 1-2 句理由（引用具体 Section/Table/Figure 作为证据）。\n\n---\n\n以下是 Reviewer 1 的完整审稿原文：\n\n### 遗留问题评估\n\n**R1-W1: Feature importance multicollinearity [PARTIALLY ADDRESSED]**\nVIF>10, W=0.90 concordance 已报告。但论文仍在 §4.2 做个体 feature 精确排名声明而未 caveat 高 VIF 下个体归属不可靠。判定：minor remaining。\n\n**R1-W3: LoRA rank sensitivity [NOT ADDRESSED]**\nr=16 是唯一值。无 r∈{4,64} ablation。LoRA rank 控制过拟合程度——若 r=4 signal 消失则 depth signal 部分来自 capacity artifact。判定：Should-Fix。\n\n**R4-N2: Zero-shot LLM framing [PARTIALLY ADDRESSED]**\n§6 Discussion 已改善。但 §5.1 标题仍为 \"Baseline Comparison\"，正文称 \"zero-shot LLM baseline\" + \"42pp gap\"。判定：Should-Fix。\n\n**R4-N3: Cross-scale qualification [PARTIALLY ADDRESSED]**\nBody 已有 qualifications，但 abstract 仍无 \"preliminary\" 限定词。判定：Should-Fix。\n\n**R5-N2: Reference model dependency [RESOLVED via Limitations]**\nLimitations 明确承认仅测试 2 个同族 reference。合理。\n\n**R5-W1: Single-generator non-independence [NOT ADDRESSED]**\n每个 depth 仅一个 LoRA instance。LOGO 排除 seed-article confound 但未 address single-generator。Limitations 未讨论。判定：Should-Fix。\n\n**R5-W2: Strategy detection prerequisite [RESOLVED]**\n§6 和 Limitations 已明确讨论 two-stage pipeline 需求。\n\n**R5-W3: FPR [PARTIALLY ADDRESSED + REGRESSED — CRITICAL NEW ISSUE]**\n**Table 12 显示 Pythia C4 FPR = 29.2%（d0 acc = 70.8%）**，但 Abstract 和 Limitations 仅报告 \"4.7% to 22.4%\"，排除了最差结果且无说明。构成选择性数据报告。\n若排除原因是 Pythia = self-reference model，则与 §3.2 \"self-model does not confer systematic advantage\" 矛盾。\n判定：Must-Fix。\n\n**R5-W5: EDD classifier-dependence [NOT ADDRESSED]**\nEDD 定义后无 \"operational measure conditioned on classifier+features\" 的声明。Table 3 间接支持但未 explicitly connected。判定：Should-Fix。\n\n### Must-Fix:\n- MF1: FPR 选择性报告——abstract/Limitations 声称 4.7%-22.4% 但 Pythia C4 = 29.2%\n\n### Should-Fix:\n- SF1: LoRA rank sensitivity 缺失\n- SF2: Single-generator non-independence 未讨论\n- SF3: EDD 未定义为 operational measure\n- SF4: Abstract 缺 \"preliminary\" for cross-scale\n- SF5: §5.1 标题 \"Baseline Comparison\" 应改为 ablation framing\n\n### New Findings:\n- N1 [critical]: FPR 数据选择性报告（与 R5-W3 合并）\n- N2 [warning]: Abstract 末尾可能存在 EDD 排版错误\n- N3 [minor]: Table 12 commentary \"d1 (2.9%), d2 (0.9%), d1 (3.1%)\" 第二个 d1 应为 d3\n\n### Overall: 3.0/5 (Borderline, 倾向 Findings)\n\n---\n\n请逐条 [AGREE] 或 [REBUT]。"
}
```

---

### Runtime record

_source line 72 · 2026-05-16T19:41:19.818Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-16T19:41:19.818Z",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

## Round 2

2 recorded events

### User

_source line 73 · 2026-05-16T19:41:19.807Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3cdf7fae-a851-4c77-8c9c-aa06dc0aa07b",
  "isSidechain": false,
  "promptId": "8674bce5-88f2-4e27-bfe5-dd671ecdcf00",
  "type": "user",
  "isMeta": true,
  "uuid": "f0e362c6-f526-4f09-b3f1-0e9dc6474b66",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 74 · 2026-05-16T19:41:19.808Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f0e362c6-f526-4f09-b3f1-0e9dc6474b66",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "166a99d5-37a2-4234-b91a-eb9215ba0a0e",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "id": "8b797314-77eb-4119-86ad-f7b3995a7938",
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

8 recorded events

### User

_source line 75 · 2026-05-16T19:41:19.877Z_

[Round 6 审稿请求]:
## 交叉分享 — Reviewer 1 的完整审稿意见

请逐条回应以下 Reviewer 1 的审稿意见。对每个观点用 **[AGREE]** 或 **[REBUT]** 标记，并提供 1-2 句理由（引用具体 Section/Table/Figure 作为证据）。

---

以下是 Reviewer 1 的完整审稿原文：

### 遗留问题评估

**R1-W1: Feature importance multicollinearity [PARTIALLY ADDRESSED]**
VIF>10, W=0.90 concordance 已报告。但论文仍在 §4.2 做个体 feature 精确排名声明而未 caveat 高 VIF 下个体归属不可靠。判定：minor remaining。

**R1-W3: LoRA rank sensitivity [NOT ADDRESSED]**
r=16 是唯一值。无 r∈{4,64} ablation。LoRA rank 控制过拟合程度——若 r=4 signal 消失则 depth signal 部分来自 capacity artifact。判定：Should-Fix。

**R4-N2: Zero-shot LLM framing [PARTIALLY ADDRESSED]**
§6 Discussion 已改善。但 §5.1 标题仍为 "Baseline Comparison"，正文称 "zero-shot LLM baseline" + "42pp gap"。判定：Should-Fix。

**R4-N3: Cross-scale qualification [PARTIALLY ADDRESSED]**
Body 已有 qualifications，但 abstract 仍无 "preliminary" 限定词。判定：Should-Fix。

**R5-N2: Reference model dependency [RESOLVED via Limitations]**
Limitations 明确承认仅测试 2 个同族 reference。合理。

**R5-W1: Single-generator non-independence [NOT ADDRESSED]**
每个 depth 仅一个 LoRA instance。LOGO 排除 seed-article confound 但未 address single-generator。Limitations 未讨论。判定：Should-Fix。

**R5-W2: Strategy detection prerequisite [RESOLVED]**
§6 和 Limitations 已明确讨论 two-stage pipeline 需求。

**R5-W3: FPR [PARTIALLY ADDRESSED + REGRESSED — CRITICAL NEW ISSUE]**
**Table 12 显示 Pythia C4 FPR = 29.2%（d0 acc = 70.8%）**，但 Abstract 和 Limitations 仅报告 "4.7% to 22.4%"，排除了最差结果且无说明。构成选择性数据报告。
若排除原因是 Pythia = self-reference model，则与 §3.2 "self-model does not confer systematic advantage" 矛盾。
判定：Must-Fix。

**R5-W5: EDD classifier-dependence [NOT ADDRESSED]**
EDD 定义后无 "operational measure conditioned on classifier+features" 的声明。Table 3 间接支持但未 explicitly connected。判定：Should-Fix。

### Must-Fix:
- MF1: FPR 选择性报告——abstract/Limitations 声称 4.7%-22.4% 但 Pythia C4 = 29.2%

### Should-Fix:
- SF1: LoRA rank sensitivity 缺失
- SF2: Single-generator non-independence 未讨论
- SF3: EDD 未定义为 operational measure
- SF4: Abstract 缺 "preliminary" for cross-scale
- SF5: §5.1 标题 "Baseline Comparison" 应改为 ablation framing

### New Findings:
- N1 [critical]: FPR 数据选择性报告（与 R5-W3 合并）
- N2 [warning]: Abstract 末尾可能存在 EDD 排版错误
- N3 [minor]: Table 12 commentary "d1 (2.9%), d2 (0.9%), d1 (3.1%)" 第二个 d1 应为 d3

### Overall: 3.0/5 (Borderline, 倾向 Findings)

---

请逐条 [AGREE] 或 [REBUT]。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "166a99d5-37a2-4234-b91a-eb9215ba0a0e",
  "isSidechain": false,
  "promptId": "8674bce5-88f2-4e27-bfe5-dd671ecdcf00",
  "type": "user",
  "uuid": "af08cb83-3a6d-4242-ad3d-e5b0fb358c68",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 76 · 2026-05-16T19:41:19.876Z_

```json
{
  "parentUuid": "af08cb83-3a6d-4242-ad3d-e5b0fb358c68",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "882dac43-85fa-4a7a-8d36-73a31be41c6b",
  "timestamp": "2026-05-16T19:41:19.876Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 77 · 2026-05-16T19:42:12.594Z_

<details><summary>Logged reasoning block</summary>

```text
Let me go through Reviewer 1's comments one by one and provide my response based on what I've read from the paper. Let me re-check some specific claims, particularly about the FPR data in Table 12.

Looking at my reading of the appendix (section_appendix.tex), the calibration table (Table \ref{tab:calibration}, which I read as lines 220-239) shows:
- Pythia-1.4B C4: d0 = 79.8%, FPR = 20.2%


- GPT-2 XL C4: d0 = 77.6%, FPR = 22.4%
- OLMo-1B C4: d0 = 95.3%, FPR = 4.7%

So the table I read shows Pythia C4 FPR = 20.2%, not 29.2%. R1 claims "Table 12 shows Pythia C4 FPR = 29.2% (d0 acc = 70.8%)" — but from what I can see in the source, Table \ref{tab:calibration} shows different values, so there's a discrepancy between what the reviewer is citing and what appears in the actual table.

The abstract and Limitations section both reference FPR ranges from 4.7% to 22.4%, which aligns with what I'm reading in the calibration table. This range includes Pythia's 20.2%, so either the reviewer is looking at a different version of the paper or made an error in their citation. Looking at the atlas.tex footnote on line 47, there's actually a caveat about multicollinearity that addresses R1's concern — it notes the high VIF values and cautions that individual feature rankings should be interpreted carefully, though it emphasizes that the group-level dominance of perplexity tail statistics holds up across different importance measures. The table and text do discuss specific feature rankings, but the caveat is there in the footnote. Now I need to check R1's point about LoRA rank.

For the LoRA rank sensitivity, I don't see any ablation study varying r across different values like 4 or 64 in the paper — the methods section only mentions r=16. This is a legitimate gap that R1 raises. Moving on to the zero-shot LLM framing issue, I'm checking the section title in generalization.tex and it's actually "Classifier Comparison and Surface-Text Ablation" rather than "Baseline Comparison" as R1 claims, though I should verify if this might be from an older version of the paper.

For the cross-scale qualification concern, I'm re-reading the abstract and it clearly states "Preliminary cross-scale observations" — so R1's claim that the abstract lacks the "preliminary" qualifier is factually wrong, and I can rebut this directly. The reference model dependency issue appears to be resolved.

On the single-generator non-independence point, R5-W1 raises a legitimate concern about whether rerunning the LoRA training with different seeds would produce different depth signals, which speaks to generalization — this is a valid weakness I should acknowledge. The strategy detection prerequisite is resolved.

For the FPR selective reporting claim, I'm checking the actual table values and finding that R1 cites 29.2% for Pythia C4, but the source shows 20.2% instead. The range mentioned in the Limitations section (4.7%-22.4%) correctly captures the min-max across the three models, so if R1's number is wrong, there's no selective reporting issue to address — I can rebut this on factual grounds.

But let me double-check whether there might be other classifier variants with higher FPR values that I'm missing. The nucleus RF table only covers nucleus classifiers, so I should verify whether temperature or top-k variants appear elsewhere in the paper.

Looking through the table structure, I can count the main tables through the generalization section, then various appendix tables including the calibration data. Without compiling the PDF myself, I can't determine the exact table numbering, but the LaTeX source clearly shows Pythia C4 at 20.2% FPR, GPT-2 XL at 22.4%, and OLMo at 4.7%. Since R1 claims 29.2% for Pythia, which doesn't match the source values, I should push back on that figure while acknowledging I'd need the compiled PDF to fully verify.

Now I'm looking at R5's claim about EDD classifier-dependence and how it's defined.

EDD relies on a specific binary Random Forest setup with 500 trees and a fixed feature selection strategy, so it's inherently tied to that classifier configuration rather than being a pure data property. Table 3 does show classifier convergence is tight across different models, which somewhat addresses the concern, but the paper doesn't explicitly frame EDD as an operational measure dependent on the classifier choice. This is a fair minor point.

For the abstract typesetting issue, I'm checking the EDD notation and don't see an obvious error in how it's formatted.

Looking at the Table 12 commentary, R1 claims there's a duplicate "d1" in the OLMo results, but when I check the actual appendix text, it clearly lists d1, d2, d3 in sequence without repetition. Either R1 is referencing a different version or misread the table, so I'll push back on this one.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "882dac43-85fa-4a7a-8d36-73a31be41c6b",
  "isSidechain": false,
  "requestId": "req_011Cb6pLddf75SFURci7T6x8",
  "type": "assistant",
  "uuid": "76101050-34c1-40be-bc9b-0d941637f6fd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHt2bGXeeLmNTiUrW8us1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1269,
      "cache_read_input_tokens": 78021,
      "output_tokens": 5242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1269,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 5242,
          "cache_read_input_tokens": 78021,
          "cache_creation_input_tokens": 1269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1269
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

_source line 78 · 2026-05-16T19:42:56.954Z_

## 交叉回应 — Reviewer 2 对 Reviewer 1 的逐条评估

---

**[AGREE] R1-W1: Feature importance multicollinearity**
同意此问题为 minor remaining。Atlas.tex §4.2 脚注确实有 caveat（"Individual feature rankings should be interpreted cautiously given high multicollinearity"），但正文仍做精确排名声明（"9/9 cells, 8/9 cells"）时未每次附带 caveat。不过由于 group-level dominance 经 permutation/SHAP/Gini 三种方法验证一致（Appendix B, Kendall's W=0.90），个体排名问题不影响核心结论。Minor。

---

**[AGREE] R1-W3: LoRA rank sensitivity**
同意这是 Should-Fix。r=16 是唯一测试值（method.tex §2.2 line 33: "r=16, α=32"）。LoRA rank 控制 fine-tuning 容量——高 rank 可能产生更强 overfitting 从而放大 depth signal，低 rank 可能减弱。不做 ablation 无法排除 "depth signal 部分来自 LoRA capacity artifact" 的可能。但此问题更偏 robustness 而非 fatal flaw——即使 signal 强度随 rank 变化，只要方向一致（monotonic decay preserved），core contribution 不受影响。

---

**[REBUT] R4-N2: Zero-shot LLM framing**
R1 称 "§5.1 标题仍为 'Baseline Comparison'"，但当前 source（generalization.tex line 7）标题为 **"Classifier Comparison and Surface-Text Ablation"**——已改为 ablation framing。正文（line 14）也明确用 "Surface-text ablation" 段落标题。若 R1 引用的是旧版本编译产物则不适用于当前版本。当前 framing 已合适。

---

**[REBUT] R4-N3: Cross-scale qualification**
R1 称 "abstract 仍无 'preliminary' 限定词"，但 abstract (line 8) **明确写了 "Preliminary cross-scale observations"**：
> "Preliminary cross-scale observations on two 7B-scale generators yield 70.2% accuracy (EDD=4) and 60.1%"

此问题已 RESOLVED，非 "PARTIALLY ADDRESSED"。

---

**[AGREE] R5-N2: Reference model dependency — RESOLVED**
同意已充分 address。Limitations §明确承认 "both reference models share similar scale (~1B) and autoregressive architecture"。

---

**[AGREE] R5-W1: Single-generator non-independence**
同意这是有效问题。每个 model-strategy 组合仅一次 LoRA training run → 5000 samples per depth 全部来自同一 checkpoint。若该 checkpoint 有 idiosyncratic behavior（如特定 LoRA seed 导致的 mode），depth signal 可能不 generalize 到同一 model 的另一次 fine-tuning。Cross-model transfer (§5.2) 部分 mitigates（不同 model 的不同 run 仍有 signal），但 within-model replication 确实缺失。建议 Limitations 加一句承认。

---

**[REBUT] R5-W3: FPR 选择性报告**
R1 的核心 claim 是 "Table 12 显示 Pythia C4 FPR = 29.2%（d0 acc = 70.8%），但 Abstract/Limitations 仅报告 4.7% to 22.4%"。

**但 LaTeX source（section_appendix.tex, tab:calibration）明确显示 Pythia C4 FPR = 20.2%（d0 acc = 79.8%），非 29.2%。** 三个模型的 FPR 分别为：
- Pythia: 20.2%
- GPT-2 XL: 22.4%  
- OLMo: 4.7%

Limitations 报告 "4.7% (OLMo) to 22.4% (GPT-2 XL)" 覆盖了完整范围（Pythia 的 20.2% 落在此区间内）。**不构成选择性报告。**

R1 的 "29.2%" 数字可能来自：(1) 阅读旧版编译 PDF 的误读，(2) 将其他表格数值混淆。建议 R1 核实具体表格和数值来源。

若此数值确认为 20.2%，则 MF1 应降级或撤销。

---

**[AGREE] R5-W5: EDD classifier-dependence**
同意这是 minor 但有效的问题。EDD 定义（method.tex Eq. 1）使用 "binary Random Forest classifier (500 trees)" 作为 discriminability measure——它是 **operational measure**（依赖 classifier + feature set），非数据的 intrinsic property。Table 5 (tab:baselines) 显示 classifier 间 ≤0.4pp 差异间接支持 EDD 的 classifier-robustness，但论文未 explicitly state "EDD is an operational metric conditioned on the chosen classifier and feature representation; the values reported should be interpreted as lower bounds on true discriminability." 一句 clarification 即可解决。

---

**[REBUT] N1: FPR 数据选择性报告**
与 R5-W3 合并回应。基于 source 验证，Pythia FPR = 20.2%（非 29.2%），报告范围 4.7%-22.4% 无遗漏。

---

**[AGREE] N2: Abstract EDD 排版不一致**
Abstract 中 "$\mathrm{EDD}_{0.75}{=}4$"（有 threshold 下标）和后续 "$\mathrm{EDD}{=}4$"（无下标）确实不一致。Minor typesetting issue。

---

**[REBUT] N3: Table commentary typo**
R1 称 text 中 "d1 (2.9%), d2 (0.9%), d1 (3.1%)" 有重复 d1。但 source（section_appendix.tex line 245）实际写的是：
> "for OLMo, d1 (2.9%), d2 (0.5%), d3 (1.3%)"

三个 depth 标签正确（d1, d2, d3），数值也无重复。R1 可能误读了编译 PDF 中的字符（d3 误读为 d1）。

---

## 总结评估

| R1 观点 | 我的判断 | 理由 |
|---------|---------|------|
| R1-W1 multicollinearity | AGREE (minor) | 有 caveat 但不够显眼 |
| R1-W3 LoRA rank | AGREE (should-fix) | 确实缺 ablation |
| R4-N2 LLM framing | REBUT | 标题已改为 ablation framing |
| R4-N3 cross-scale prelim | REBUT | Abstract 已有 "Preliminary" |
| R5-W1 single-generator | AGREE (should-fix) | 有效 concern，建议 Limitations 加 1 句 |
| R5-W3/N1 FPR selective | REBUT | Source 显示 20.2% 非 29.2%，范围正确 |
| R5-W5 EDD operational | AGREE (minor) | 缺 1 句 explicit statement |
| N2 EDD typo | AGREE (minor) | 下标不一致 |
| N3 Table typo | REBUT | Source 无此错误 |

**R1 的 Must-Fix (MF1: FPR selective reporting) 基于错误数值，应降级。** 其他 Should-Fix 中 LoRA rank sensitivity 和 single-generator non-independence 是有效问题但不影响 accept/reject decision——它们限制 generalizability claim 的强度但不 invalidate core findings。

R1 给出 3.0/5 (Borderline/Findings)，与我的评估一致。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "76101050-34c1-40be-bc9b-0d941637f6fd",
  "isSidechain": false,
  "requestId": "req_011Cb6pLddf75SFURci7T6x8",
  "type": "assistant",
  "uuid": "f12dec18-93b2-4eb4-80de-36ed167cecec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHt2bGXeeLmNTiUrW8us1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1269,
      "cache_read_input_tokens": 78021,
      "output_tokens": 5242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1269,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 5242,
          "cache_read_input_tokens": 78021,
          "cache_creation_input_tokens": 1269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1269
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

_source line 79 · 2026-05-16T19:43:06.766Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_011pUFSmUBuF56Rc6B3GYSsg`</summary>

```json
{
  "text": "## Round 6 交叉回应 — Reviewer 2 对 Reviewer 1 的逐条评估\n\n### 汇总\n\n对 R1 的 9 个观点：**5 个 AGREE，4 个 REBUT**。\n\n关键分歧：\n1. **R1 的 Must-Fix (FPR selective reporting) 基于错误数值**：R1 称 \"Table 12 Pythia C4 FPR = 29.2%\"，但 LaTeX source (tab:calibration) 明确显示 **20.2%**（d0 acc = 79.8%）。报告范围 \"4.7%-22.4%\" 完整覆盖三个模型，不构成选择性报告。建议 R1 核实数据来源。\n2. **R1 称 abstract 无 \"preliminary\"**：实际 abstract line 8 已写 \"Preliminary cross-scale observations\"。\n3. **R1 称 §5.1 标题为 \"Baseline Comparison\"**：当前 source 标题为 \"Classifier Comparison and Surface-Text Ablation\"。\n\n同意的有效问题：\n- LoRA rank sensitivity（should-fix, robustness concern）\n- Single-generator non-independence（should-fix, 可加 1 句 Limitations）\n- EDD 未声明为 operational measure（minor）\n\n### 整体判断\n\nR1 与我给出相同评分 (3.0/5, Findings-level)，核心共识：\n- 实验系统性好但 novelty 有限\n- 当前 framing 偏乐观\n- 适合 Findings 而非 Main Conference\n\n但 R1 的唯一 Must-Fix 可能基于数据误读，若确认则论文的 \"critical issues\" 实际更少，更倾向于 solid Findings paper。",
  "reviewer_id": "2",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f12dec18-93b2-4eb4-80de-36ed167cecec",
  "isSidechain": false,
  "requestId": "req_011Cb6pLddf75SFURci7T6x8",
  "type": "assistant",
  "uuid": "dcc551a3-7bdc-4a12-ba98-e42c86041a0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHt2bGXeeLmNTiUrW8us1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1269,
      "cache_read_input_tokens": 78021,
      "output_tokens": 5242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1269,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 5242,
          "cache_read_input_tokens": 78021,
          "cache_creation_input_tokens": 1269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1269
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

_source line 80_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 6 审稿请求]: ## 交叉分享 — Reviewer 1 的完整审稿意见  请逐条回应以下 Reviewer 1 的审稿意见。对每个观点用 **[AGREE]** 或 **[REBUT]** 标记，并提供 1-2 句理由（引用具体 Section/Table/Figure 作为证据）。  ---  以下是 Reviewer 1 的完整审稿原文：  ### 遗留问题评估  **R1-…",
  "leafUuid": "dcc551a3-7bdc-4a12-ba98-e42c86041a0f",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Runtime record

_source line 81_

```json
{
  "type": "ai-title",
  "aiTitle": "Review Round 6: EMNLP submission novelty and Related Work check",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe"
}
```

---

### Tool result

_source line 82 · 2026-05-16T19:43:10.428Z_

<details><summary>↩ Tool result · `toolu_011pUFSmUBuF56Rc6B3GYSsg`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dcc551a3-7bdc-4a12-ba98-e42c86041a0f",
  "isSidechain": false,
  "promptId": "8674bce5-88f2-4e27-bfe5-dd671ecdcf00",
  "type": "user",
  "uuid": "0cb36b40-701a-416d-bbaf-cad232df8552",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "dcc551a3-7bdc-4a12-ba98-e42c86041a0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "ac6e46b8-dc91-491c-a79b-86b8c3d644fe",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

# Research conversation: [Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1 **你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性** ### Venue 信息 - **目标会议**：EMNLP 2026 M

**How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 96
- **Recorded user turns:** 3
- **Tool calls:** 29
- **Original source:** `logs/chats/exported-trajectories/account-3/18e2781e-e5ad-47ad-895c-aafdbd2b04f0.jsonl`
- **Structured JSON:** [`7a8b6e1c04912e2f621e.json`](../../sessions/7a/7a8b6e1c04912e2f621e.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-19T02:58:07.105Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-19T02:58:07.105Z",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "content": "[Round 1 审稿请求]:\n## Round 1 审稿任务 — Reviewer 1\n\n**你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**\n\n### Venue 信息\n- **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿)\n- **截止日期**：2026-05-25\n- **页数限制**：Long paper 8 pages content；Limitations 和 Ethics Statement 不计入页数\n- **模板**：ACL style (`\\usepackage[review]{acl}`)\n- **匿名规则**：Double-blind\n- **评分标准**：5=Award, 4.5=Borderline Award, 4=Conference, 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1.5=Resubmit after next cycle, 1=Do not resubmit\n\n### 论文文件\n- 主文件：`projects/recursive_gen_depth_est/docs/paper/main.tex`\n- 各章节：abstract.tex, introduction.tex, related_work.tex, method.tex, theory.tex, atlas.tex, generalization.tex, discussion.tex, conclusion.tex, section_appendix.tex\n\n### 你的审查重点\n\n1. **方法设计**：\n   - 问题定义（ordinal classification formalization）是否严谨\n   - EDD 定义（Definition 1, Eq. 1）是否数学上合理\n   - 19 个统计特征的设计是否有理论依据和实验支撑\n   - RF 分类器选择是否合理，序数结构是否被正确利用\n\n2. **实验设计**：\n   - Benchmark 构建（3×3 grid, 180K samples）是否可靠\n   - 交叉验证方案是否正确（是否存在数据泄露风险）\n   - Cross-model / Cross-strategy / Cross-scale 实验设计是否合理\n   - Baseline 选择是否充分、对比是否公平\n   - Confound 分析是否到位\n\n3. **统计有效性**：\n   - 报告的数字是否可信（CI, p-value, effect size）\n   - d0 对 headline metrics 的膨胀效应是否被充分揭示\n   - 多重比较是否需要校正\n   - 样本量是否足够支撑 claims\n\n4. **可复现性**：\n   - 超参数是否完整列出\n   - 计算资源是否报告\n   - 数据/代码是否承诺公开\n\n### 输出格式\n\n请按以下结构输出审稿意见：\n```\n## Summary (2-3 句)\n## Strengths (逐条)\n## Weaknesses (逐条，标注 [Must-Fix] / [Should-Fix] / [Minor])\n## Questions (需要作者回答的问题)\n## Missing References (遗漏的重要文献)\n## Overall Assessment (评分 + 置信度)\n## Detailed Comments (逐 section 的细节意见)\n```"
}
````

---

### Runtime record

_source line 2 · 2026-05-19T02:58:07.109Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-19T02:58:07.109Z",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

## Round 1

87 recorded events

### User

_source line 3 · 2026-05-19T02:58:07.143Z_

[Round 1 审稿请求]:
## Round 1 审稿任务 — Reviewer 1

**你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**

### Venue 信息
- **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿)
- **截止日期**：2026-05-25
- **页数限制**：Long paper 8 pages content；Limitations 和 Ethics Statement 不计入页数
- **模板**：ACL style (`\usepackage[review]{acl}`)
- **匿名规则**：Double-blind
- **评分标准**：5=Award, 4.5=Borderline Award, 4=Conference, 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1.5=Resubmit after next cycle, 1=Do not resubmit

### 论文文件
- 主文件：`projects/recursive_gen_depth_est/docs/paper/main.tex`
- 各章节：abstract.tex, introduction.tex, related_work.tex, method.tex, theory.tex, atlas.tex, generalization.tex, discussion.tex, conclusion.tex, section_appendix.tex

### 你的审查重点

1. **方法设计**：
   - 问题定义（ordinal classification formalization）是否严谨
   - EDD 定义（Definition 1, Eq. 1）是否数学上合理
   - 19 个统计特征的设计是否有理论依据和实验支撑
   - RF 分类器选择是否合理，序数结构是否被正确利用

2. **实验设计**：
   - Benchmark 构建（3×3 grid, 180K samples）是否可靠
   - 交叉验证方案是否正确（是否存在数据泄露风险）
   - Cross-model / Cross-strategy / Cross-scale 实验设计是否合理
   - Baseline 选择是否充分、对比是否公平
   - Confound 分析是否到位

3. **统计有效性**：
   - 报告的数字是否可信（CI, p-value, effect size）
   - d0 对 headline metrics 的膨胀效应是否被充分揭示
   - 多重比较是否需要校正
   - 样本量是否足够支撑 claims

4. **可复现性**：
   - 超参数是否完整列出
   - 计算资源是否报告
   - 数据/代码是否承诺公开

### 输出格式

请按以下结构输出审稿意见：
```
## Summary (2-3 句)
## Strengths (逐条)
## Weaknesses (逐条，标注 [Must-Fix] / [Should-Fix] / [Minor])
## Questions (需要作者回答的问题)
## Missing References (遗漏的重要文献)
## Overall Assessment (评分 + 置信度)
## Detailed Comments (逐 section 的细节意见)
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "160613c5-3030-442c-9f27-67aee2c32e65",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-19T02:58:07.143Z_

```json
{
  "parentUuid": "160613c5-3030-442c-9f27-67aee2c32e65",
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
  "uuid": "6b50da44-138f-4b85-af54-566d173cd825",
  "timestamp": "2026-05-19T02:58:07.143Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-19T02:58:07.143Z_

```json
{
  "parentUuid": "6b50da44-138f-4b85-af54-566d173cd825",
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
  "uuid": "019665f2-ef65-4f8c-b1da-0f85e0dce360",
  "timestamp": "2026-05-19T02:58:07.143Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-19T02:58:07.143Z_

```json
{
  "parentUuid": "019665f2-ef65-4f8c-b1da-0f85e0dce360",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "f0308b9d-9c75-4009-ac43-8610089f00a2",
  "timestamp": "2026-05-19T02:58:07.143Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
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
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Assistant

_source line 8 · 2026-05-19T02:58:10.624Z_

我先执行 session 启动初始化，然后开始审稿。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f0308b9d-9c75-4009-ac43-8610089f00a2",
  "isSidechain": false,
  "requestId": "req_011CbBBGKBFNXbwKKajVZee7",
  "type": "assistant",
  "uuid": "d1eae194-3c09-4076-92e7-632593da4cf1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017XK35G3oxvsmuc65C44UyK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15730,
      "cache_read_input_tokens": 11841,
      "output_tokens": 81,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15730,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 81,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 15730,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15730
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

_source line 9 · 2026-05-19T02:58:10.708Z_

<details open><summary>🔧 Tool call — Skill · `toolu_01G1aF4JBKQe2SGwxeDcFnYq`</summary>

```json
{
  "skill": "review-reviewer-session-start"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d1eae194-3c09-4076-92e7-632593da4cf1",
  "isSidechain": false,
  "requestId": "req_011CbBBGKBFNXbwKKajVZee7",
  "type": "assistant",
  "uuid": "fcfc27d1-d4d5-442d-a501-99fa3d141ef3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017XK35G3oxvsmuc65C44UyK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15730,
      "cache_read_input_tokens": 11841,
      "output_tokens": 81,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15730,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 81,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 15730,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15730
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

_source line 10 · 2026-05-19T02:58:10.712Z_

<details><summary>↩ Tool result · reported error · `toolu_01G1aF4JBKQe2SGwxeDcFnYq`</summary>

```text
&lt;tool_use_error>Unknown skill: review-reviewer-session-start&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fcfc27d1-d4d5-442d-a501-99fa3d141ef3",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "343461eb-bbc8-4901-a404-c0d8cda40f3b",
  "toolUseResult": "Error: Unknown skill: review-reviewer-session-start",
  "sourceToolAssistantUUID": "fcfc27d1-d4d5-442d-a501-99fa3d141ef3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-19T02:58:14.265Z_

<details><summary>Logged reasoning block</summary>

```text
The skill isn't available via the Skill tool. Let me read the skill file directly and follow its instructions.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "343461eb-bbc8-4901-a404-c0d8cda40f3b",
  "isSidechain": false,
  "requestId": "req_011CbBBGadRr5DE4QuinMUp1",
  "type": "assistant",
  "uuid": "aa0c8bd6-195a-48af-8dd7-5d91e9ec9b14",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGCBxnepFc8M12bqCamG1a",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 125,
      "cache_read_input_tokens": 27571,
      "output_tokens": 157,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 125,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 157,
          "cache_read_input_tokens": 27571,
          "cache_creation_input_tokens": 125,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 125
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

_source line 12 · 2026-05-19T02:58:14.799Z_

让我读取启动初始化 skill 文件并按指示执行。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "aa0c8bd6-195a-48af-8dd7-5d91e9ec9b14",
  "isSidechain": false,
  "requestId": "req_011CbBBGadRr5DE4QuinMUp1",
  "type": "assistant",
  "uuid": "8447cd18-c45f-4c9c-86ed-f0389f02943a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGCBxnepFc8M12bqCamG1a",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 125,
      "cache_read_input_tokens": 27571,
      "output_tokens": 157,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 125,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 157,
          "cache_read_input_tokens": 27571,
          "cache_creation_input_tokens": 125,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 125
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

_source line 13 · 2026-05-19T02:58:16.672Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DKqktviEo1iQbb3FbFxQoF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/skills/review-reviewer-session-start.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8447cd18-c45f-4c9c-86ed-f0389f02943a",
  "isSidechain": false,
  "requestId": "req_011CbBBGadRr5DE4QuinMUp1",
  "type": "assistant",
  "uuid": "4ecb6b22-1c86-4b27-95f4-4fcb9ba7dde3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGCBxnepFc8M12bqCamG1a",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 125,
      "cache_read_input_tokens": 27571,
      "output_tokens": 157,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 125,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 157,
          "cache_read_input_tokens": 27571,
          "cache_creation_input_tokens": 125,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 125
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

_source line 14 · 2026-05-19T02:58:16.691Z_

<details><summary>↩ Tool result · reported error · `toolu_01DKqktviEo1iQbb3FbFxQoF`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4ecb6b22-1c86-4b27-95f4-4fcb9ba7dde3",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "12b3131e-19f9-415e-a968-c813ec62c76e",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335.",
  "sourceToolAssistantUUID": "4ecb6b22-1c86-4b27-95f4-4fcb9ba7dde3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-19T02:58:19.993Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01EcoTTgXcfmCL7V2KiCPuHq`</summary>

```json
{
  "pattern": "**/review-reviewer-session-start*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "12b3131e-19f9-415e-a968-c813ec62c76e",
  "isSidechain": false,
  "requestId": "req_011CbBBH3UU7weLhLgAfMwof",
  "type": "assistant",
  "uuid": "58a99082-754e-42d2-847f-29770cf0d74b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012znmj6ZhoU1SDWQLMYRFQ8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 232,
      "cache_read_input_tokens": 27696,
      "output_tokens": 96,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 232,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 96,
          "cache_read_input_tokens": 27696,
          "cache_creation_input_tokens": 232,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 232
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

_source line 16 · 2026-05-19T02:58:20.048Z_

<details><summary>↩ Tool result · `toolu_01EcoTTgXcfmCL7V2KiCPuHq`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "58a99082-754e-42d2-847f-29770cf0d74b",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "f4b8b566-be66-40fb-b44b-5d5de17c0c6b",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 46,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "58a99082-754e-42d2-847f-29770cf0d74b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-19T02:58:23.544Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01TsCmKzYRveCGSgXDdxpZBA`</summary>

```json
{
  "pattern": "**/review-reviewer-session-start*",
  "path": "/home/ubuntu/agent-ml-research"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f4b8b566-be66-40fb-b44b-5d5de17c0c6b",
  "isSidechain": false,
  "requestId": "req_011CbBBHGGuMRY4mGAqnmSzU",
  "type": "assistant",
  "uuid": "fb9c0d17-a03d-4ea2-9a50-19a9fcc2b360",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EzM6YwSR28TABrmco9GfjX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 111,
      "cache_read_input_tokens": 27928,
      "output_tokens": 87,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 111,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 87,
          "cache_read_input_tokens": 27928,
          "cache_creation_input_tokens": 111,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 111
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

_source line 18 · 2026-05-19T02:58:23.715Z_

<details><summary>↩ Tool result · `toolu_01TsCmKzYRveCGSgXDdxpZBA`</summary>

```text
/home/ubuntu/agent-ml-research/skills/global/review-reviewer-session-start.skill.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fb9c0d17-a03d-4ea2-9a50-19a9fcc2b360",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "0dfe74f8-586e-4efd-a847-40ac86abb4d3",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/agent-ml-research/skills/global/review-reviewer-session-start.skill.md"
    ],
    "durationMs": 165,
    "numFiles": 1,
    "truncated": false
  },
  "sourceToolAssistantUUID": "fb9c0d17-a03d-4ea2-9a50-19a9fcc2b360",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-19T02:58:26.093Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LpFVUMyMsw5jzjsnrM2u2q`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/review-reviewer-session-start.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0dfe74f8-586e-4efd-a847-40ac86abb4d3",
  "isSidechain": false,
  "requestId": "req_011CbBBHYKJXrYfKtVag41WS",
  "type": "assistant",
  "uuid": "0d6b1eb8-bb62-4256-860d-dd061b2c91a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WmYCbMsk6DXchdrgAZHFGZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 124,
      "cache_read_input_tokens": 28039,
      "output_tokens": 78,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 124,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 78,
          "cache_read_input_tokens": 28039,
          "cache_creation_input_tokens": 124,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 124
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

_source line 20 · 2026-05-19T02:58:26.107Z_

<details><summary>↩ Tool result · `toolu_01LpFVUMyMsw5jzjsnrM2u2q`</summary>

```text
1	---
2	name: review-reviewer-session-start
3	description: Review Reviewer session 启动初始化——检查论文格式、编译状态、材料清单。Review Reviewer 角色 session 启动时自动使用。
4	priority: 8
5	scope: global
6	tags:
7	- workflow
8	- review
9	- session
10	version: 2
11	roles: []
12	---
13	
14	# Review Reviewer Session 启动流程
15	
16	执行顺序：
17	1. 读取论文文件（`projects/{project}/paper/main.tex` 或类似路径）
18	2. 检查论文格式状态：
19	   - 页数是否在 venue 要求内（若已知 venue）
20	   - LaTeX 是否可编译（调用 `ssh_execute` 运行 `pdflatex` 或 `latexmk`）
21	   - 图表是否有标题和标签
22	3. 视觉检查：如果已有编译好的 PDF，使用 `paper-visual-review` skill 渲染关键页面（首页、图表页、参考文献页），检查排版溢出、公式渲染、图表质量等视觉问题
23	4. 检查投稿材料清单：
24	   - cover letter 是否存在
25	   - 补充材料是否准备
26	   - 参考文献格式是否正确
27	5. 向 Review Director 汇报（`review_reviewer_post_to_director`）：
28	   - 论文当前状态
29	   - 发现的格式问题（如有）
30	   - 视觉检查结果（如有）
31	   - 缺少的材料（如有）
32	
33	此流程在 Review Director 分配任务后执行。
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0d6b1eb8-bb62-4256-860d-dd061b2c91a3",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "17e89ca4-50c3-4b87-8cbd-914e0001f92d",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/review-reviewer-session-start.skill.md",
      "content": "---\nname: review-reviewer-session-start\ndescription: Review Reviewer session 启动初始化——检查论文格式、编译状态、材料清单。Review Reviewer 角色 session 启动时自动使用。\npriority: 8\nscope: global\ntags:\n- workflow\n- review\n- session\nversion: 2\nroles: []\n---\n\n# Review Reviewer Session 启动流程\n\n执行顺序：\n1. 读取论文文件（`projects/{project}/paper/main.tex` 或类似路径）\n2. 检查论文格式状态：\n   - 页数是否在 venue 要求内（若已知 venue）\n   - LaTeX 是否可编译（调用 `ssh_execute` 运行 `pdflatex` 或 `latexmk`）\n   - 图表是否有标题和标签\n3. 视觉检查：如果已有编译好的 PDF，使用 `paper-visual-review` skill 渲染关键页面（首页、图表页、参考文献页），检查排版溢出、公式渲染、图表质量等视觉问题\n4. 检查投稿材料清单：\n   - cover letter 是否存在\n   - 补充材料是否准备\n   - 参考文献格式是否正确\n5. 向 Review Director 汇报（`review_reviewer_post_to_director`）：\n   - 论文当前状态\n   - 发现的格式问题（如有）\n   - 视觉检查结果（如有）\n   - 缺少的材料（如有）\n\n此流程在 Review Director 分配任务后执行。\n",
      "numLines": 34,
      "startLine": 1,
      "totalLines": 34
    }
  },
  "sourceToolAssistantUUID": "0d6b1eb8-bb62-4256-860d-dd061b2c91a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-19T02:58:31.047Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to start my review. Let me first:
1. Read the main.tex and all chapter files to understand the paper
2. Search for ACL ARR reviewer guidelines

Let me start by reading the paper files and searching for reviewer guidelines in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "17e89ca4-50c3-4b87-8cbd-914e0001f92d",
  "isSidechain": false,
  "requestId": "req_011CbBBHiKKV4pPf6m27napd",
  "type": "assistant",
  "uuid": "db758485-87bf-468f-8bc7-e2e861d28cd4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015zdoYnUbyAKPVWHtHd4wV2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 614,
      "cache_read_input_tokens": 28163,
      "output_tokens": 187,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 614,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 187,
          "cache_read_input_tokens": 28163,
          "cache_creation_input_tokens": 614,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 614
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

_source line 22 · 2026-05-19T02:58:32.083Z_

开始审稿。先并行读取论文各章节和搜索 ARR reviewer guidelines。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "db758485-87bf-468f-8bc7-e2e861d28cd4",
  "isSidechain": false,
  "requestId": "req_011CbBBHiKKV4pPf6m27napd",
  "type": "assistant",
  "uuid": "3173352a-c884-4cbf-84f2-c23818077c42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015zdoYnUbyAKPVWHtHd4wV2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 614,
      "cache_read_input_tokens": 28163,
      "output_tokens": 187,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 614,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 187,
          "cache_read_input_tokens": 28163,
          "cache_creation_input_tokens": 614,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 614
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

_source line 23 · 2026-05-19T02:58:32.581Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NaLcE86PtscKy4tSkSBPot`</summary>

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
  "parentUuid": "3173352a-c884-4cbf-84f2-c23818077c42",
  "isSidechain": false,
  "requestId": "req_011CbBBHiKKV4pPf6m27napd",
  "type": "assistant",
  "uuid": "dc150e28-dc5e-4eff-a99a-84a153ff7850",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015zdoYnUbyAKPVWHtHd4wV2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 614,
      "cache_read_input_tokens": 28163,
      "output_tokens": 187,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 614,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 187,
          "cache_read_input_tokens": 28163,
          "cache_creation_input_tokens": 614,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 614
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

_source line 24 · 2026-05-19T02:58:32.587Z_

<details><summary>↩ Tool result · `toolu_01NaLcE86PtscKy4tSkSBPot`</summary>

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
17	\usepackage{enumitem}
18	\usepackage{amsthm}
19	
20	\theoremstyle{definition}
21	\newtheorem{definition}{Definition}
22	
23	\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\via Statistical Fingerprints}
24	
25	\author{Anonymous}
26	
27	\begin{document}
28	\maketitle
29	
30	\input{abstract}
31	
32	\input{introduction}
33	
34	\input{related_work}
35	
36	\input{method}
37	
38	\input{theory}
39	
40	\input{atlas}
41	
42	\input{generalization}
43	
44	\input{discussion}
45	
46	\input{conclusion}
47	
48	\bibliography{references}
49	
50	\appendix
51	\input{section_appendix}
52	
53	\end{document}
54	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dc150e28-dc5e-4eff-a99a-84a153ff7850",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "7e7c0685-bd29-4fd9-ba57-f543a5148d87",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex",
      "content": "% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\n% Target: EMNLP 2026 (ARR May cycle)\n\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{enumitem}\n\\usepackage{amsthm}\n\n\\theoremstyle{definition}\n\\newtheorem{definition}{Definition}\n\n\\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\\\via Statistical Fingerprints}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{method}\n\n\\input{theory}\n\n\\input{atlas}\n\n\\input{generalization}\n\n\\input{discussion}\n\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{section_appendix}\n\n\\end{document}\n",
      "numLines": 54,
      "startLine": 1,
      "totalLines": 54
    }
  },
  "sourceToolAssistantUUID": "dc150e28-dc5e-4eff-a99a-84a153ff7850",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 25_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**  ### Venue 信息 - **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿) - **截止日期**：2026-05-25 - **页数限制**：Long paper 8 pag…",
  "leafUuid": "7e7c0685-bd29-4fd9-ba57-f543a5148d87",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Runtime record

_source line 26_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Tool call

_source line 27 · 2026-05-19T02:58:43.577Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01D1VFJ5DhER5Z75JS9SYvZH`</summary>

```json
{
  "pattern": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7e7c0685-bd29-4fd9-ba57-f543a5148d87",
  "isSidechain": false,
  "requestId": "req_011CbBBJC99DmFFTiG8xiSC7",
  "type": "assistant",
  "uuid": "d57072c2-eb90-4e1e-87c7-cfe8d54c5b7e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yrPaxufzw7NU3UHcL9dwy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 669,
      "cache_read_input_tokens": 28777,
      "output_tokens": 102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 669,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 102,
          "cache_read_input_tokens": 28777,
          "cache_creation_input_tokens": 669,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 669
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

_source line 28 · 2026-05-19T02:58:43.588Z_

<details><summary>↩ Tool result · `toolu_01D1VFJ5DhER5Z75JS9SYvZH`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/theory.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d57072c2-eb90-4e1e-87c7-cfe8d54c5b7e",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "971c2fca-406b-4755-9bf7-d5609b9b0b1e",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/theory.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex"
    ],
    "durationMs": 8,
    "numFiles": 11,
    "truncated": false
  },
  "sourceToolAssistantUUID": "d57072c2-eb90-4e1e-87c7-cfe8d54c5b7e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 29 · 2026-05-19T02:58:43.729Z_

```json
{
  "parentUuid": "971c2fca-406b-4755-9bf7-d5609b9b0b1e",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "197a9376-d87c-4bea-a627-ae50d3abdc14",
  "timestamp": "2026-05-19T02:58:43.729Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 30 · 2026-05-19T02:58:47.595Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01P7A43U4ThZ1boXJa6FCcfD`</summary>

```json
{
  "query": "select:WebSearch,TodoWrite,mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "197a9376-d87c-4bea-a627-ae50d3abdc14",
  "isSidechain": false,
  "requestId": "req_011CbBBK1WxGT8iUnmMAA9Uq",
  "type": "assistant",
  "uuid": "59030cb1-7765-4537-bbd6-f10b06211980",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M7eqjpUBJ8FTeHwhRkfKMF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 639,
      "cache_read_input_tokens": 29446,
      "output_tokens": 125,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 639,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 125,
          "cache_read_input_tokens": 29446,
          "cache_creation_input_tokens": 639,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 639
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

_source line 31 · 2026-05-19T02:58:47.606Z_

<details><summary>↩ Tool result · `toolu_01P7A43U4ThZ1boXJa6FCcfD`</summary>

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
  "tool_name": "TodoWrite"
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

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__verify_references"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "59030cb1-7765-4537-bbd6-f10b06211980",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "8fbb498c-021d-428f-aad4-a1a2a5ba6226",
  "toolUseResult": {
    "matches": [
      "WebSearch",
      "TodoWrite",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "query": "select:WebSearch,TodoWrite,mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "59030cb1-7765-4537-bbd6-f10b06211980",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 32 · 2026-05-19T02:58:51.753Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read all the paper sections in parallel, search for ARR reviewer guidelines, and verify references.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8fbb498c-021d-428f-aad4-a1a2a5ba6226",
  "isSidechain": false,
  "requestId": "req_011CbBBKJNDUEmyQGXxZt4ZR",
  "type": "assistant",
  "uuid": "c6a7173b-e3c0-4030-885d-e3ec1feb9fc4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B7vtaMpoTWpvA7GUUyVL81",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3992,
      "cache_read_input_tokens": 30085,
      "output_tokens": 278,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3992,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 278,
          "cache_read_input_tokens": 30085,
          "cache_creation_input_tokens": 3992,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3992
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

_source line 33 · 2026-05-19T02:58:52.709Z_

开始并行读取论文各章节、搜索 ARR reviewer guidelines、验证引用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c6a7173b-e3c0-4030-885d-e3ec1feb9fc4",
  "isSidechain": false,
  "requestId": "req_011CbBBKJNDUEmyQGXxZt4ZR",
  "type": "assistant",
  "uuid": "1838e39b-e67a-4118-890e-798f24924112",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B7vtaMpoTWpvA7GUUyVL81",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3992,
      "cache_read_input_tokens": 30085,
      "output_tokens": 278,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3992,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 278,
          "cache_read_input_tokens": 30085,
          "cache_creation_input_tokens": 3992,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3992
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

_source line 34 · 2026-05-19T02:58:55.378Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01BS6MesoR9dEvbu2YQduFM7`</summary>

```json
{
  "todos": [
    {
      "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
      "status": "in_progress",
      "activeForm": "搜索 ACL ARR reviewer guidelines"
    },
    {
      "content": "通读论文全文（所有章节）",
      "status": "pending",
      "activeForm": "通读论文全文"
    },
    {
      "content": "验证引用完整性和真实性",
      "status": "pending",
      "activeForm": "验证引用"
    },
    {
      "content": "撰写审稿意见并汇报 Director",
      "status": "pending",
      "activeForm": "撰写审稿意见"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1838e39b-e67a-4118-890e-798f24924112",
  "isSidechain": false,
  "requestId": "req_011CbBBKJNDUEmyQGXxZt4ZR",
  "type": "assistant",
  "uuid": "273e765d-770f-4ace-b4ee-c10a26206028",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B7vtaMpoTWpvA7GUUyVL81",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3992,
      "cache_read_input_tokens": 30085,
      "output_tokens": 278,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3992,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 278,
          "cache_read_input_tokens": 30085,
          "cache_creation_input_tokens": 3992,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3992
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

_source line 35 · 2026-05-19T02:58:55.382Z_

<details><summary>↩ Tool result · `toolu_01BS6MesoR9dEvbu2YQduFM7`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "273e765d-770f-4ace-b4ee-c10a26206028",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "b685d2f6-754f-4fbd-9d71-e4419e7b14f0",
  "toolUseResult": {
    "oldTodos": [],
    "newTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "in_progress",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "pending",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "pending",
        "activeForm": "验证引用"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "pending",
        "activeForm": "撰写审稿意见"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "273e765d-770f-4ace-b4ee-c10a26206028",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-19T02:58:59.758Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XBijupWKsi4yjjMDvxNjQq`</summary>

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
  "parentUuid": "b685d2f6-754f-4fbd-9d71-e4419e7b14f0",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "2fe04cd7-78d4-4fb8-ab87-e249148fce9e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 37 · 2026-05-19T02:58:59.764Z_

<details><summary>↩ Tool result · `toolu_01XBijupWKsi4yjjMDvxNjQq`</summary>

```text
1	\begin{abstract}
2	As large language models increasingly train on web text containing their own outputs, a recursive model$\to$data$\to$model loop arises, yet no method estimates how many such iterations a text has undergone.
3	We formalize \emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.
4	A Random Forest over 19 statistical features achieves $\approx$69--86\% four-class accuracy on 1--1.5B base models under matched decoding strategies (chance = 25\%; d1--d3 balanced accuracy: 71.6\% within-distribution, 55.4\% cross-model; chance = 33\%), with perplexity tail statistics as consistent depth markers; a parsimonious subset of 5 features retains 97.6\% of full performance.
5	We define the \emph{Effective Discriminable Depth} (EDD) metric, finding $\mathrm{EDD}_{0.70}{=}4$ for all three families at the primary scale (confirmed by 5-class d0--d4 extension on three families, 71--80\%), and show that cross-model transfer reaches 66.4\% (2.7$\times$ chance).
6	Systematic generalization across eight axes (e.g., cross-scale 7--14B (70\%$\to$54\%, attenuating with scale), prompted generation at 69.5\%, cross-model chains at 84.75\%, and cross-domain arXiv at 74.1\%) confirms that depth signal is robust across model families but scale- and strategy-dependent, residing in distributional statistics inaccessible from surface text or binary detection scores (zero-shot LLMs: 30--36\%; membership inference baselines: 30--33\%; both $>$43\,pp below RF).
7	\end{abstract}
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2fe04cd7-78d4-4fb8-ab87-e249148fce9e",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "1aaa8239-eb99-447f-a83d-a987c4b9c8c6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises, yet no method estimates how many such iterations a text has undergone.\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.\nA Random Forest over 19 statistical features achieves $\\approx$69--86\\% four-class accuracy on 1--1.5B base models under matched decoding strategies (chance = 25\\%; d1--d3 balanced accuracy: 71.6\\% within-distribution, 55.4\\% cross-model; chance = 33\\%), with perplexity tail statistics as consistent depth markers; a parsimonious subset of 5 features retains 97.6\\% of full performance.\nWe define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.70}{=}4$ for all three families at the primary scale (confirmed by 5-class d0--d4 extension on three families, 71--80\\%), and show that cross-model transfer reaches 66.4\\% (2.7$\\times$ chance).\nSystematic generalization across eight axes (e.g., cross-scale 7--14B (70\\%$\\to$54\\%, attenuating with scale), prompted generation at 69.5\\%, cross-model chains at 84.75\\%, and cross-domain arXiv at 74.1\\%) confirms that depth signal is robust across model families but scale- and strategy-dependent, residing in distributional statistics inaccessible from surface text or binary detection scores (zero-shot LLMs: 30--36\\%; membership inference baselines: 30--33\\%; both $>$43\\,pp below RF).\n\\end{abstract}\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "2fe04cd7-78d4-4fb8-ab87-e249148fce9e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-19T02:59:00.249Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Jxv8JSb5rWh8JA1KtoDCfJ`</summary>

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
  "parentUuid": "1aaa8239-eb99-447f-a83d-a987c4b9c8c6",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "d696d5b2-70a2-4a50-b25c-6fd61e76c32a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 39 · 2026-05-19T02:59:00.255Z_

<details><summary>↩ Tool result · `toolu_01Jxv8JSb5rWh8JA1KtoDCfJ`</summary>

```text
1	\section{Introduction}
2	\label{sec:intro}
3	
4	The text on which large language models are trained increasingly contains their own outputs.
5	As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
6	This model$\to$data$\to$model cycle is no longer hypothetical; it is already occurring in the wild. Yet whether the recursive generation depth of a text can be estimated from its statistical properties remains unstudied, a question that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
7	
8	Existing tools address adjacent but distinct problems.
9	Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
10	Watermarking \cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.
11	The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
12	No existing method estimates the ordinal recursive generation depth of a text passage from its content alone.
13	
14	We find that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \textbf{consistent in direction but scale-dependent in magnitude} across the three model families and three decoding strategies studied.
15	Specifically, perplexity tail statistics (the 90th-percentile perplexity, \texttt{p90\_ppl}, and surprisal variance, \texttt{var\_surprisal}) emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.
16	Instruction-tuned variants exhibit monotonically decreasing AUC (regularization), whereas base models can show non-monotonic trajectories; instruction tuning thus acts as a regularizer on the depth signal rather than a source of degradation.
17	
18	This paper is an empirical study and problem formalization rather than an algorithmic contribution.
19	We formalize recursive generation depth estimation as ordinal classification and introduce a lightweight pipeline: compute 19 reference-model statistical features (effective dimensionality ${\approx}$4--5 due to multicollinearity; \S\ref{sec:atlas:features}) and classify with a Random Forest into $K{+}1$ depth classes.
20	To characterize how recursive generation reshapes these features, we construct the \emph{Depth Degradation Atlas}: a $3 \times 3$ grid of model families $\times$ decoding strategies spanning 4 depths (180K samples).
21	The atlas reveals strategy-dependent degradation trajectories and we introduce the \emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.
22	
23	Our contributions are:
24	\begin{itemize}[nosep,leftmargin=*]
25	    \item \textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark ($3$ model families $\times$ $3$ decoding strategies $\times$ $4$ depths).
26	
27	    \item \textbf{Depth Degradation Atlas.} Perplexity tail statistics dominate depth discrimination (top-2 in 9/9 and 8/9 cells); $\mathrm{EDD}_{0.70}{=}4$ for all three families, validated by 5-class (d0--d4) extension on three families (71--80\%); at the stricter $T{=}0.75$, Pythia achieves $p{=}0.001$ with graded confidence across families in the d3--d4 region.
28	
29	    \item \textbf{Generalization and cross-strategy analysis.} Cross-model LOO 66.4\% (d1--d3: 55.4\%), cross-seed replication across three families, prompted 69.5\%, cross-scale 7--14B (54--70\%, attenuating with scale), cross-domain arXiv 74.1\%. Cross-strategy transfer (59.1\%) reveals a structural difficulty: different decoding strategies induce qualitatively distinct degradation trajectories, with d1/d2 boundary inversion under strategy mismatch. Surface-text controls (zero-shot LLMs 30--36\%) and binary detection/membership inference baselines (DetectGPT, Min-K\% Prob: 30--33\%) confirm the signal resides in distributional statistics inaccessible from surface text or detection scores.
30	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d696d5b2-70a2-4a50-b25c-6fd61e76c32a",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "907c8b2c-e5b4-4c2d-b8bb-832c98a331d7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical; it is already occurring in the wild. Yet whether the recursive generation depth of a text can be estimated from its statistical properties remains unstudied, a question that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive generation depth of a text passage from its content alone.\n\nWe find that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \\textbf{consistent in direction but scale-dependent in magnitude} across the three model families and three decoding strategies studied.\nSpecifically, perplexity tail statistics (the 90th-percentile perplexity, \\texttt{p90\\_ppl}, and surprisal variance, \\texttt{var\\_surprisal}) emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.\nInstruction-tuned variants exhibit monotonically decreasing AUC (regularization), whereas base models can show non-monotonic trajectories; instruction tuning thus acts as a regularizer on the depth signal rather than a source of degradation.\n\nThis paper is an empirical study and problem formalization rather than an algorithmic contribution.\nWe formalize recursive generation depth estimation as ordinal classification and introduce a lightweight pipeline: compute 19 reference-model statistical features (effective dimensionality ${\\approx}$4--5 due to multicollinearity; \\S\\ref{sec:atlas:features}) and classify with a Random Forest into $K{+}1$ depth classes.\nTo characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families $\\times$ decoding strategies spanning 4 depths (180K samples).\nThe atlas reveals strategy-dependent degradation trajectories and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark ($3$ model families $\\times$ $3$ decoding strategies $\\times$ $4$ depths).\n\n    \\item \\textbf{Depth Degradation Atlas.} Perplexity tail statistics dominate depth discrimination (top-2 in 9/9 and 8/9 cells); $\\mathrm{EDD}_{0.70}{=}4$ for all three families, validated by 5-class (d0--d4) extension on three families (71--80\\%); at the stricter $T{=}0.75$, Pythia achieves $p{=}0.001$ with graded confidence across families in the d3--d4 region.\n\n    \\item \\textbf{Generalization and cross-strategy analysis.} Cross-model LOO 66.4\\% (d1--d3: 55.4\\%), cross-seed replication across three families, prompted 69.5\\%, cross-scale 7--14B (54--70\\%, attenuating with scale), cross-domain arXiv 74.1\\%. Cross-strategy transfer (59.1\\%) reveals a structural difficulty: different decoding strategies induce qualitatively distinct degradation trajectories, with d1/d2 boundary inversion under strategy mismatch. Surface-text controls (zero-shot LLMs 30--36\\%) and binary detection/membership inference baselines (DetectGPT, Min-K\\% Prob: 30--33\\%) confirm the signal resides in distributional statistics inaccessible from surface text or detection scores.\n\\end{itemize}",
      "numLines": 30,
      "startLine": 1,
      "totalLines": 30
    }
  },
  "sourceToolAssistantUUID": "d696d5b2-70a2-4a50-b25c-6fd61e76c32a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-19T02:59:00.728Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WorgnYeUqCWBHxzPREGGAA`</summary>

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
  "parentUuid": "907c8b2c-e5b4-4c2d-b8bb-832c98a331d7",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "3cd690f0-4d81-4482-99c2-2dc7009d73b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 41 · 2026-05-19T02:59:00.732Z_

<details><summary>↩ Tool result · `toolu_01WorgnYeUqCWBHxzPREGGAA`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\paragraph{Model Collapse Theory.}
5	Recursive training on model outputs erodes distributional tails \cite{shumailov2024_nature}, an effect formalized as exponential tail decay via scaling laws \cite{dohmatob2024_tale_of_tails,seddik2024synthetic} and extended to autophagous loops in the MAD framework \cite{alemohammad2024_mad}.
6	Subsequent work refines the conditions under which collapse occurs: \citet{bertrand2024_stability} identify convergence to a fixed point under mixed real-synthetic retraining (providing theoretical grounding for our EDD ceiling, \S\ref{sec:method:theory}), \citet{shi2025_closer_look} reframe collapse as a generalization-to-memorization transition, and \citet{dohmatob2025_strong_collapse} extend guarantees to broader model classes.
7	Mitigation \cite{gerstgrasser2024_accumulate,drayson2025_detection_prevents_collapse,yi2026_escaping_collapse,falahati2026_curated,wenzek2020_ccnet}, non-monotonic dynamics \cite{bakshi2026_collapse_improvement}, convergence analysis \cite{marchi2024_heat_death,wang2026_contamination,knowledge_collapse2025,dohmatob2024_demystified}, and diversity decline \cite{guo2024curious,briesch2024selfconsuming,padmakumar2024diversity,sigma2026_spectral,synthetic_eggs2026} are active areas.
8	\citet{schaeffer2025} argue that ``model collapse'' conflates multiple phenomena and call for operationally precise metrics; we respond by operationalizing tail-erosion predictions into a deployable ordinal classifier, revealing strategy-dependent trajectories and non-monotonic 7B behavior that the theory does not predict.
9	All assume depth is known a priori; we address the inverse problem of estimating depth from text alone.
10	
11	\paragraph{AI Text Detection.}
12	The detection literature \cite{wu2025_detection_survey} spans statistical methods (DetectGPT \cite{mitchell2023_detectgpt}, Fast-DetectGPT \cite{fast_detectgpt2024}, Binoculars \cite{binoculars2024}, DivEye \cite{diveye2026}, BiScope \cite{guo2024_biscope}, GLTR \cite{gehrmann2019_gltr}, Ghostbuster \cite{verma2024_ghostbuster}, DNA-GPT \cite{yang2024_dnagpt}), geometric approaches based on intrinsic dimensionality \cite{tulchinskii2023_intrinsic_dim}, and watermarking \cite{kirchenbauer2023_watermark}, with known limits from paraphrasing \cite{sadasivan2023_paraphrase}, distribution shift \cite{pudasaini2026_detection_fails}, and generator barriers \cite{pu2026_generator_barrier}.
13	M4-SemEval \cite{wang2024_m4_semeval}, RAID \cite{dugan2024_raid}, and MAGE \cite{li2024_mage} benchmark detection across domains, models, and adversarial conditions.
14	\citet{bevendorff2025_two_paradigms} distinguish authorship attribution (which model?) from verification (human or AI?); depth estimation introduces a third axis: which recursive iteration.
15	All these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.
16	
17	\paragraph{Membership Inference and Data Provenance.}
18	Min-K\% Prob \cite{shi2024_minkprob} detects pretraining membership via low-probability token statistics, related to our perplexity features but limited to binary classification; cryptographically undetectable watermarks \cite{christ2024_undetectable} require generator cooperation.
19	Depth estimation occupies a distinct niche: ordinal, retroactive, and cooperation-free.
20	
21	\paragraph{Adjacent Tasks.}
22	EditLens \cite{editlens2026} estimates editing extent but does not model recursive chains; \citet{uchendu2020_attribution} classify \emph{which} model generated text; \citet{mohamed2025_broken_telephone} characterize \emph{how} text degrades under iterative generation without classifying which iteration a passage comes from.
23	Our task performs the inverse: ordinal depth estimation from text alone.
24	
25	\paragraph{Ordinal Classification.}
26	CORAL \cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \cite{cloc2025} extends contrastive learning with multi-margin ordinal losses; \citet{kasa2024_ordinality} benchmark ordinal techniques for NLP; \citet{janitza2016_ordinal_rf} show RF implicitly respects ordinal structure when inter-class distances are monotonic.
27	We adopt CORAL and CLOC as baselines (\S\ref{sec:generalization}).
28	
29	\paragraph{Decoding Strategy Effects.}
30	Decoding strategies shape text statistics in ways that interact with depth signals \cite{holtzman2020_nucleus,finlayson2024_closing,garces_arias2025_decoding_decoded,wiher2022_decoding,basu2021_mirostat}.
31	Our atlas (\S\ref{sec:atlas}) shows these strategies induce qualitatively different degradation trajectories under recursive generation.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3cd690f0-4d81-4482-99c2-2dc7009d73b2",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "3b53fbd3-8689-454b-9ea1-ff02fcd7837c",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Model Collapse Theory.}\nRecursive training on model outputs erodes distributional tails \\cite{shumailov2024_nature}, an effect formalized as exponential tail decay via scaling laws \\cite{dohmatob2024_tale_of_tails,seddik2024synthetic} and extended to autophagous loops in the MAD framework \\cite{alemohammad2024_mad}.\nSubsequent work refines the conditions under which collapse occurs: \\citet{bertrand2024_stability} identify convergence to a fixed point under mixed real-synthetic retraining (providing theoretical grounding for our EDD ceiling, \\S\\ref{sec:method:theory}), \\citet{shi2025_closer_look} reframe collapse as a generalization-to-memorization transition, and \\citet{dohmatob2025_strong_collapse} extend guarantees to broader model classes.\nMitigation \\cite{gerstgrasser2024_accumulate,drayson2025_detection_prevents_collapse,yi2026_escaping_collapse,falahati2026_curated,wenzek2020_ccnet}, non-monotonic dynamics \\cite{bakshi2026_collapse_improvement}, convergence analysis \\cite{marchi2024_heat_death,wang2026_contamination,knowledge_collapse2025,dohmatob2024_demystified}, and diversity decline \\cite{guo2024curious,briesch2024selfconsuming,padmakumar2024diversity,sigma2026_spectral,synthetic_eggs2026} are active areas.\n\\citet{schaeffer2025} argue that ``model collapse'' conflates multiple phenomena and call for operationally precise metrics; we respond by operationalizing tail-erosion predictions into a deployable ordinal classifier, revealing strategy-dependent trajectories and non-monotonic 7B behavior that the theory does not predict.\nAll assume depth is known a priori; we address the inverse problem of estimating depth from text alone.\n\n\\paragraph{AI Text Detection.}\nThe detection literature \\cite{wu2025_detection_survey} spans statistical methods (DetectGPT \\cite{mitchell2023_detectgpt}, Fast-DetectGPT \\cite{fast_detectgpt2024}, Binoculars \\cite{binoculars2024}, DivEye \\cite{diveye2026}, BiScope \\cite{guo2024_biscope}, GLTR \\cite{gehrmann2019_gltr}, Ghostbuster \\cite{verma2024_ghostbuster}, DNA-GPT \\cite{yang2024_dnagpt}), geometric approaches based on intrinsic dimensionality \\cite{tulchinskii2023_intrinsic_dim}, and watermarking \\cite{kirchenbauer2023_watermark}, with known limits from paraphrasing \\cite{sadasivan2023_paraphrase}, distribution shift \\cite{pudasaini2026_detection_fails}, and generator barriers \\cite{pu2026_generator_barrier}.\nM4-SemEval \\cite{wang2024_m4_semeval}, RAID \\cite{dugan2024_raid}, and MAGE \\cite{li2024_mage} benchmark detection across domains, models, and adversarial conditions.\n\\citet{bevendorff2025_two_paradigms} distinguish authorship attribution (which model?) from verification (human or AI?); depth estimation introduces a third axis: which recursive iteration.\nAll these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.\n\n\\paragraph{Membership Inference and Data Provenance.}\nMin-K\\% Prob \\cite{shi2024_minkprob} detects pretraining membership via low-probability token statistics, related to our perplexity features but limited to binary classification; cryptographically undetectable watermarks \\cite{christ2024_undetectable} require generator cooperation.\nDepth estimation occupies a distinct niche: ordinal, retroactive, and cooperation-free.\n\n\\paragraph{Adjacent Tasks.}\nEditLens \\cite{editlens2026} estimates editing extent but does not model recursive chains; \\citet{uchendu2020_attribution} classify \\emph{which} model generated text; \\citet{mohamed2025_broken_telephone} characterize \\emph{how} text degrades under iterative generation without classifying which iteration a passage comes from.\nOur task performs the inverse: ordinal depth estimation from text alone.\n\n\\paragraph{Ordinal Classification.}\nCORAL \\cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \\cite{cloc2025} extends contrastive learning with multi-margin ordinal losses; \\citet{kasa2024_ordinality} benchmark ordinal techniques for NLP; \\citet{janitza2016_ordinal_rf} show RF implicitly respects ordinal structure when inter-class distances are monotonic.\nWe adopt CORAL and CLOC as baselines (\\S\\ref{sec:generalization}).\n\n\\paragraph{Decoding Strategy Effects.}\nDecoding strategies shape text statistics in ways that interact with depth signals \\cite{holtzman2020_nucleus,finlayson2024_closing,garces_arias2025_decoding_decoded,wiher2022_decoding,basu2021_mirostat}.\nOur atlas (\\S\\ref{sec:atlas}) shows these strategies induce qualitatively different degradation trajectories under recursive generation.",
      "numLines": 31,
      "startLine": 1,
      "totalLines": 31
    }
  },
  "sourceToolAssistantUUID": "3cd690f0-4d81-4482-99c2-2dc7009d73b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 42 · 2026-05-19T02:59:01.204Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JJfzWPUG4cVao5zVvUfgwX`</summary>

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
  "parentUuid": "3b53fbd3-8689-454b-9ea1-ff02fcd7837c",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "859f4306-1ac1-4f5f-8213-f9063ff11ac0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 43 · 2026-05-19T02:59:01.209Z_

<details><summary>↩ Tool result · `toolu_01JJfzWPUG4cVao5zVvUfgwX`</summary>

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
33	Starting from a Wikipedia subset ($\mathcal{D}_0$), each cycle: (1)~LoRA finetuning \cite{hu2022lora} on $\mathcal{D}_{k-1}$ ($r{=}16$, $\alpha{=}32$, lr $2{\times}10^{-4}$, effective batch 16, 3 epochs, dropout $0.05$; fresh adapter from the base model at each depth; full protocol in Appendix~\ref{app:lora_protocol}); (2)~sampling 5{,}000 passages (max 512 tokens, BOS-seeded) under the specified strategy; (3)~$\mathcal{D}_k$ feeds the next cycle.
34	Each depth is produced by a model trained on prior-depth data, not by sampling from the unmodified base model.
35	BOS-seeded generation may amplify depth signal; prompted-generation validation (\S\ref{sec:gen:crossstrategy}) confirms signal persistence ($-$13.8\,pp).
36	No per-passage lineage exists across depths; cross-validation splits do not introduce leakage.
37	
38	\paragraph{Reference model.}
39	All statistical features (\S\ref{sec:method:features}) use Pythia-1.4B as fixed reference model; this overlaps with one generator but confers no systematic advantage (Pythia 78.7\% vs.\ GPT-2~XL 85.9\%).
40	Alternative references yield 67--79\% (Appendix~\ref{app:ref_ablation}; Limitations).
41	
42	\subsection{Statistical Feature Design}
43	\label{sec:method:features}
44	
45	We extract a feature vector $\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\S\ref{sec:atlas:features}) shows the top 5 achieve 97.6\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features; effective independent dimensionality is ${\approx}$4--5.
46	The features fall into four categories (Table~\ref{tab:features}).
47	
48	\begin{table}[t]
49	\centering
50	\small
51	\caption{The 19 statistical features comprising $\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}
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
71	\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments and quantiles (p10--p90); tail quantiles are especially informative as recursive finetuning erodes the high-perplexity tail (\S\ref{sec:atlas}).
72	\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\log p(\text{token})$.
73	\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.
74	\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \in \{2, 3, 4\}$.
75	
76	\subsection{Effective Discriminable Depth}
77	\label{sec:method:edd}
78	
79	Aggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.
80	We propose the \emph{Effective Discriminable Depth} (EDD) as an operational measure of how far into a recursive chain adjacent depths remain distinguishable.
81	
82	\paragraph{Pairwise discriminability.}
83	Let $\mathcal{D} = \{0, 1, \dots, K\}$ denote the depth set and $T \in (0.5, 1.0]$ a discrimination threshold.
84	For each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\lfloor\sqrt{19}\rfloor$ candidate features per split) trained on class-balanced data from $\mathbf{f}(x)$ (\S\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.
85	Each pair uses an independent classifier to avoid decision boundary dilution from multi-class settings.
86	
87	\begin{definition}[Effective Discriminable Depth]
88	\label{def:edd}
89	The \emph{Effective Discriminable Depth} at threshold $T$ is:
90	\begin{multline}
91	\mathrm{EDD}_T = \max \bigl\{ d^*{+}1 \,:\, \\
92	\forall\, d' \leq d^*,\; \mathrm{AUC}(d', d'{+}1) \geq T \bigr\}
93	\label{eq:edd}
94	\end{multline}
95	where $d^* \in \{0, \dots, K{-}1\}$. If\, $\mathrm{AUC}(0,1) < T$, then $\mathrm{EDD}_T = 0$.
96	\end{definition}
97	
98	$\mathrm{EDD}_T$ reports the longest \emph{contiguous} discriminable prefix: the deepest $d$ such that every pair from $(0,1)$ through $(d{-}1, d)$ exceeds $T$.\footnote{AUC profiles decay monotonically for 1--1.5B models (\S\ref{sec:atlas}); Qwen2.5-7B shows non-monotonic patterns (\S\ref{sec:gen:crossscale}), where the contiguous formulation is more conservative (Limitations).}
99	We report $T{=}0.70$ as primary threshold (8/9 cells achieve $\mathrm{EDD} \geq 3$); sensitivity at $T \in \{0.65, 0.70, 0.75, 0.80\}$ in \S\ref{sec:atlas}.
100	
101	\paragraph{Classifiers.}
102	Our primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold CV).\footnote{EDD binary classifiers use 500 trees; the main 4-class RF uses 200 trees.}
103	The RF implicitly respects ordinal structure: 98.2\% of errors fall on adjacent depths ($|\Delta| \leq 1$), QWK\,=\,0.89; CORAL ordinal regression matches within 0.6\,pp ($p > 0.05$; \S\ref{sec:generalization}).
104	Comparisons against CORAL \cite{coral2020}, DivEye \cite{diveye2026}, and other baselines appear in \S\ref{sec:generalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "859f4306-1ac1-4f5f-8213-f9063ff11ac0",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "5687a18b-4188-41a4-9e77-59ff078dc8a4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Problem Definition}\n\\label{sec:method:problem}\n\nLet $f_\\theta$ denote a language model and $\\mathcal{D}_0$ a corpus of human-written seed text.\nWe define a \\emph{recursive generation chain} of depth $K$ as the sequence $\\mathcal{D}_0, \\mathcal{D}_1, \\dots, \\mathcal{D}_K$, where each $\\mathcal{D}_k$ ($k \\geq 1$) is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$ and sampling from the resulting model.\nDepth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \\geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.\n\nGiven a text passage $x$, the task is to estimate its recursive generation depth $d \\in \\{0, 1, \\dots, K\\}$.\nThis is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.\n\n\\subsection{Multi-Generational Benchmark Construction}\n\\label{sec:method:benchmark}\n\nWe construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.\n\n\\paragraph{Model families.}\nWe select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).\nRestricting to a narrow parameter range isolates the effect of architecture and training data from scale.\n\n\\paragraph{Decoding strategies.}\nEach model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\nThese span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.\nOur findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.\n\n\\paragraph{Depth and scale.}\nThe primary benchmark covers depths d0--d3 across all $3 \\times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).\nFor depth extension experiments (\\S\\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.\n\n\\paragraph{Generation pipeline.}\nStarting from a Wikipedia subset ($\\mathcal{D}_0$), each cycle: (1)~LoRA finetuning \\cite{hu2022lora} on $\\mathcal{D}_{k-1}$ ($r{=}16$, $\\alpha{=}32$, lr $2{\\times}10^{-4}$, effective batch 16, 3 epochs, dropout $0.05$; fresh adapter from the base model at each depth; full protocol in Appendix~\\ref{app:lora_protocol}); (2)~sampling 5{,}000 passages (max 512 tokens, BOS-seeded) under the specified strategy; (3)~$\\mathcal{D}_k$ feeds the next cycle.\nEach depth is produced by a model trained on prior-depth data, not by sampling from the unmodified base model.\nBOS-seeded generation may amplify depth signal; prompted-generation validation (\\S\\ref{sec:gen:crossstrategy}) confirms signal persistence ($-$13.8\\,pp).\nNo per-passage lineage exists across depths; cross-validation splits do not introduce leakage.\n\n\\paragraph{Reference model.}\nAll statistical features (\\S\\ref{sec:method:features}) use Pythia-1.4B as fixed reference model; this overlaps with one generator but confers no systematic advantage (Pythia 78.7\\% vs.\\ GPT-2~XL 85.9\\%).\nAlternative references yield 67--79\\% (Appendix~\\ref{app:ref_ablation}; Limitations).\n\n\\subsection{Statistical Feature Design}\n\\label{sec:method:features}\n\nWe extract a feature vector $\\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\\S\\ref{sec:atlas:features}) shows the top 5 achieve 97.6\\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features; effective independent dimensionality is ${\\approx}$4--5.\nThe features fall into four categories (Table~\\ref{tab:features}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{The 19 statistical features comprising $\\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}\n\\label{tab:features}\n\\begin{tabular}{@{}llr@{}}\n\\toprule\nCategory & Features & $n$ \\\\\n\\midrule\nPerplexity & mean, var, skewness, kurtosis, & 9 \\\\\nstatistics & p10, p25, p50, p75, p90 & \\\\\n\\addlinespace\nSurprisal & mean, var, entropy & 3 \\\\\nstatistics & & \\\\\n\\addlinespace\nLexical & type--token ratio, hapax ratio, & 4 \\\\\ndiversity & bigram entropy, trigram entropy & \\\\\n\\addlinespace\nRepetition & repeated 2/3/4-gram fractions & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments and quantiles (p10--p90); tail quantiles are especially informative as recursive finetuning erodes the high-perplexity tail (\\S\\ref{sec:atlas}).\n\\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\\log p(\\text{token})$.\n\\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.\n\\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \\in \\{2, 3, 4\\}$.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:method:edd}\n\nAggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.\nWe propose the \\emph{Effective Discriminable Depth} (EDD) as an operational measure of how far into a recursive chain adjacent depths remain distinguishable.\n\n\\paragraph{Pairwise discriminability.}\nLet $\\mathcal{D} = \\{0, 1, \\dots, K\\}$ denote the depth set and $T \\in (0.5, 1.0]$ a discrimination threshold.\nFor each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\\lfloor\\sqrt{19}\\rfloor$ candidate features per split) trained on class-balanced data from $\\mathbf{f}(x)$ (\\S\\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.\nEach pair uses an independent classifier to avoid decision boundary dilution from multi-class settings.\n\n\\begin{definition}[Effective Discriminable Depth]\n\\label{def:edd}\nThe \\emph{Effective Discriminable Depth} at threshold $T$ is:\n\\begin{multline}\n\\mathrm{EDD}_T = \\max \\bigl\\{ d^*{+}1 \\,:\\, \\\\\n\\forall\\, d' \\leq d^*,\\; \\mathrm{AUC}(d', d'{+}1) \\geq T \\bigr\\}\n\\label{eq:edd}\n\\end{multline}\nwhere $d^* \\in \\{0, \\dots, K{-}1\\}$. If\\, $\\mathrm{AUC}(0,1) < T$, then $\\mathrm{EDD}_T = 0$.\n\\end{definition}\n\n$\\mathrm{EDD}_T$ reports the longest \\emph{contiguous} discriminable prefix: the deepest $d$ such that every pair from $(0,1)$ through $(d{-}1, d)$ exceeds $T$.\\footnote{AUC profiles decay monotonically for 1--1.5B models (\\S\\ref{sec:atlas}); Qwen2.5-7B shows non-monotonic patterns (\\S\\ref{sec:gen:crossscale}), where the contiguous formulation is more conservative (Limitations).}\nWe report $T{=}0.70$ as primary threshold (8/9 cells achieve $\\mathrm{EDD} \\geq 3$); sensitivity at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ in \\S\\ref{sec:atlas}.\n\n\\paragraph{Classifiers.}\nOur primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold CV).\\footnote{EDD binary classifiers use 500 trees; the main 4-class RF uses 200 trees.}\nThe RF implicitly respects ordinal structure: 98.2\\% of errors fall on adjacent depths ($|\\Delta| \\leq 1$), QWK\\,=\\,0.89; CORAL ordinal regression matches within 0.6\\,pp ($p > 0.05$; \\S\\ref{sec:generalization}).\nComparisons against CORAL \\cite{coral2020}, DivEye \\cite{diveye2026}, and other baselines appear in \\S\\ref{sec:generalization}.",
      "numLines": 104,
      "startLine": 1,
      "totalLines": 104
    }
  },
  "sourceToolAssistantUUID": "859f4306-1ac1-4f5f-8213-f9063ff11ac0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 44 · 2026-05-19T02:59:01.682Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KjMA5sR2fq7t5bUtuDmdPB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/theory.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5687a18b-4188-41a4-9e77-59ff078dc8a4",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "6f0f0585-4b5b-44cd-938c-e55facd4e161",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 45 · 2026-05-19T02:59:01.688Z_

<details><summary>↩ Tool result · `toolu_01KjMA5sR2fq7t5bUtuDmdPB`</summary>

```text
1	\subsection{Theoretical Grounding}
2	\label{sec:method:theory}
3	
4	Recursive generation contracts the support of the learned distribution, with low-probability tokens lost first \cite{shumailov2024_nature}: tail mass $P_k(\mathrm{ppl} > t)$ decreases monotonically in depth $k$.
5	This tail erosion predicts \texttt{p90\_ppl} as a depth marker, confirmed by its top-2 ranking in all 9 cells (\S\ref{sec:atlas:features}).
6	Surprisal variance captures complementary distributional narrowing: as the support contracts, per-token surprise becomes more predictable.
7	
8	\paragraph{EDD upper bound.}
9	Tail mass at depth $k$ scales as $\alpha^k$ for a contraction factor $\alpha \in (0,1)$ \cite{dohmatob2024_tale_of_tails}; EDD reaches its upper bound when adjacent-depth feature distance falls below classifier resolution.
10	Our empirical AUC-excess contraction (ratio 0.80 at d1v2$\to$d2v3, 0.69 at d3v4$\to$d4v5; \S\ref{sec:atlas:edd}) is consistent with geometric decay approaching a fixed point \cite{bertrand2024_stability}.
11	5-class extensions to d4 (71--80\%, chance = 20\%; Appendix~\ref{app:depth4_ext}) confirm depth~4 discriminability; mean perplexity saturates before tail statistics, placing a physical ceiling on EDD.
12	
13	\paragraph{Scale-dependent attenuation.}
14	Larger models approximate the training distribution more faithfully per step ($\alpha$ closer to 1), so EDD should decrease with scale.
15	Qwen2.5-14B confirms this: d0-vs-d1 AUC drops to 0.643 (vs.\ ${>}0.99$ at 1--1.5B), while d1--d3 AUCs remain above 0.70 (\S\ref{sec:gen:crossscale}).
16	
17	\paragraph{Strategy-dependent convergence.}
18	The contraction rate $\alpha$ varies with decoding strategy.
19	Temperature scaling ($\tau < 1$) sharpens the logit distribution uniformly and accelerates convergence to the mode; temperature depth-$d$ text should therefore resemble nucleus depth-$(d{+}1)$ text in tail statistics.
20	GPT-2~XL confirms this: temperature d1 median \texttt{p90\_ppl} (92.2) matches the nucleus d2 median (92.3, IQR 75.8--112.5).
21	Top-$k$ truncation removes the low-probability tokens that carry depth signal, predicting weaker discriminability; top-$k$ cells yield the lowest accuracy (68.9--75.8\%) across the atlas (\S\ref{sec:atlas:strategy}).
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6f0f0585-4b5b-44cd-938c-e55facd4e161",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "aa11863e-9142-439c-a982-84f736e1e63e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/theory.tex",
      "content": "\\subsection{Theoretical Grounding}\n\\label{sec:method:theory}\n\nRecursive generation contracts the support of the learned distribution, with low-probability tokens lost first \\cite{shumailov2024_nature}: tail mass $P_k(\\mathrm{ppl} > t)$ decreases monotonically in depth $k$.\nThis tail erosion predicts \\texttt{p90\\_ppl} as a depth marker, confirmed by its top-2 ranking in all 9 cells (\\S\\ref{sec:atlas:features}).\nSurprisal variance captures complementary distributional narrowing: as the support contracts, per-token surprise becomes more predictable.\n\n\\paragraph{EDD upper bound.}\nTail mass at depth $k$ scales as $\\alpha^k$ for a contraction factor $\\alpha \\in (0,1)$ \\cite{dohmatob2024_tale_of_tails}; EDD reaches its upper bound when adjacent-depth feature distance falls below classifier resolution.\nOur empirical AUC-excess contraction (ratio 0.80 at d1v2$\\to$d2v3, 0.69 at d3v4$\\to$d4v5; \\S\\ref{sec:atlas:edd}) is consistent with geometric decay approaching a fixed point \\cite{bertrand2024_stability}.\n5-class extensions to d4 (71--80\\%, chance = 20\\%; Appendix~\\ref{app:depth4_ext}) confirm depth~4 discriminability; mean perplexity saturates before tail statistics, placing a physical ceiling on EDD.\n\n\\paragraph{Scale-dependent attenuation.}\nLarger models approximate the training distribution more faithfully per step ($\\alpha$ closer to 1), so EDD should decrease with scale.\nQwen2.5-14B confirms this: d0-vs-d1 AUC drops to 0.643 (vs.\\ ${>}0.99$ at 1--1.5B), while d1--d3 AUCs remain above 0.70 (\\S\\ref{sec:gen:crossscale}).\n\n\\paragraph{Strategy-dependent convergence.}\nThe contraction rate $\\alpha$ varies with decoding strategy.\nTemperature scaling ($\\tau < 1$) sharpens the logit distribution uniformly and accelerates convergence to the mode; temperature depth-$d$ text should therefore resemble nucleus depth-$(d{+}1)$ text in tail statistics.\nGPT-2~XL confirms this: temperature d1 median \\texttt{p90\\_ppl} (92.2) matches the nucleus d2 median (92.3, IQR 75.8--112.5).\nTop-$k$ truncation removes the low-probability tokens that carry depth signal, predicting weaker discriminability; top-$k$ cells yield the lowest accuracy (68.9--75.8\\%) across the atlas (\\S\\ref{sec:atlas:strategy}).\n",
      "numLines": 22,
      "startLine": 1,
      "totalLines": 22
    }
  },
  "sourceToolAssistantUUID": "6f0f0585-4b5b-44cd-938c-e55facd4e161",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 46 · 2026-05-19T02:59:02.189Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NCdxuGnZQKsQ9VwN5AfWq3`</summary>

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
  "parentUuid": "aa11863e-9142-439c-a982-84f736e1e63e",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "e87c5788-dd90-4113-9193-da52b894f3d0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 47 · 2026-05-19T02:59:02.199Z_

<details><summary>↩ Tool result · `toolu_01NCdxuGnZQKsQ9VwN5AfWq3`</summary>

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
12	Accuracy ranges from 68.9\% (Pythia, top-$k$) to 85.9\% (GPT-2~XL, temperature), all exceeding the 25\% chance baseline by a wide margin.
13	Two axis effects emerge.
14	GPT-2~XL achieves the highest accuracy under every strategy (75.8--85.9\%), followed by OLMo (74.4--82.3\%) and Pythia (68.9--78.7\%).
15	Top-$k$ sampling yields the lowest accuracy in every model.
16	The mean within-model strategy gap is 9.3~pp, comparable to the 7.2~pp mean within-strategy model gap; decoding strategy and model family contribute roughly equally to performance variance.
17	
18	\begin{table}[t]
19	\centering
20	\small
21	\caption{Four-class RF accuracy (\%) with bootstrap 95\% CI (${\pm}$half-width; $B{=}1{,}000$). RF with 200 trees, evaluated via 5-fold stratified CV (seed=42). Parenthesized: d1--d3 balanced accuracy from the same 4-class RF (chance = 25\% / 33\%). Depth-0 recall exceeds 97\% in all cells. Within-distribution ordinal quality: MAE\,=\,0.23, QWK\,=\,0.89 (QWK$_{\text{d1--d3}}$\,=\,0.74); 98.2\% of errors fall on adjacent depths ($|\Delta| \leq 1$).}
22	\label{tab:main_matrix}
23	\resizebox{\columnwidth}{!}{%
24	\begin{tabular}{@{}lccc@{}}
25	\toprule
26	& Nucleus & Temp.\ $\tau{=}0.9$ & Top-$k$ \\
27	\midrule
28	Pythia-1.4B  & 78.7{\scriptsize$\pm$0.6}\,(71.8) & 76.8{\scriptsize$\pm$0.6}\,(69.3) & 68.9{\scriptsize$\pm$0.6}\,(58.9) \\
29	OLMo-1B     & 78.9{\scriptsize$\pm$0.6}\,(72.7) & 82.3{\scriptsize$\pm$0.5}\,(76.6) & 74.4{\scriptsize$\pm$0.6}\,(66.2) \\
30	GPT-2~XL    & \textbf{84.3}{\scriptsize$\pm$0.5}\,(79.6) & \textbf{85.9}{\scriptsize$\pm$0.4}\,(81.5) & \textbf{75.8}{\scriptsize$\pm$0.6}\,(68.1) \\
31	\bottomrule
32	\end{tabular}}
33	\end{table}
34	
35	\paragraph{Per-class recall.}
36	Depth-0 recall exceeds 97\% in all 9 cells.
37	Among generated depths, d2 consistently yields the lowest recall (44--73\%), followed by d3 (61--80\%) and d1 (72--91\%).
38	The d2 trough reflects its position at the center of the depth gradient, where features overlap with both d1 and d3, consistent with d2-vs-d3 as the EDD bottleneck (\S\ref{sec:atlas:edd}).
39	Full per-class recall appears in Appendix~\ref{app:per_class}.
40	
41	%% ----------------------------------------------------------------
42	\subsection{Feature Consistency Across the Grid}
43	\label{sec:atlas:features}
44	
45	Despite the 17.1~pp accuracy spread across cells, a small feature family dominates in every setting.
46	Perplexity tail statistics as a feature group dominate depth discrimination: the 90th-percentile perplexity (\texttt{p90\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\texttt{var\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\ref{app:permutation}).\footnote{Individual feature rankings should be interpreted cautiously given high multicollinearity (VIF${>}$10 for 14--16/19 features); the group-level dominance of perplexity tail statistics is robust across importance measures.}
47	Table~\ref{tab:feature_importance} shows the full per-cell ranking.
48	
49	Cross-model feature-rank Spearman correlation averages $\bar{\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.
50	Among strategies, top-$k$ yields the highest cross-model rank correlation ($\rho = 0.811$): the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\S\ref{sec:atlas:strategy}).
51	
52	Feature ablation confirms this concentration: the top-5 features achieve 97.6\% of full accuracy (76.5\% vs.\ 78.4\%), with perplexity statistics alone reaching 76.6\% (vs.\ surprisal 73.2\%, other categories ${\leq}$47\%).
53	
54	The feature hierarchy shifts with depth.
55	At shallow boundaries (d1 vs.\ d2), \texttt{var\_surprisal} dominates importance; at deeper boundaries (d3 vs.\ d4, d4 vs.\ d5), tail perplexity statistics (\texttt{p90\_ppl}, \texttt{kurtosis\_ppl}) take over.
56	This transition aligns with model-collapse dynamics~\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).
57	
58	\begin{table}[t]
59	\centering
60	\small
61	\caption{Top-5 features by Gini importance. \textbf{Bold}: top-2. \texttt{p90\_ppl} top-2 in 9/9; \texttt{var\_surprisal} 8/9 under SHAP (7/9 under Gini).}
62	\label{tab:feature_importance}
63	\resizebox{\columnwidth}{!}{%
64	\begin{tabular}{@{}l l@{}}
65	\toprule
66	Cell & Top-5 features (Gini importance, ranked) \\
67	\midrule
68	Pythia, nuc.       & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.15)}, m\_ppl\,(.11), var\_ppl\,(.08), p75\,(.07) \\
69	Pythia, $\tau$     & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.14)}, m\_ppl\,(.11), p75\,(.07), m\_surp\,(.07) \\
70	Pythia, top-$k$    & \textbf{var\_surp\,(.16)}, \textbf{p90\_ppl\,(.12)}, m\_ppl\,(.11), var\_ppl\,(.07), m\_surp\,(.06) \\
71	GPT-2\,XL, nuc.    & \textbf{var\_surp\,(.21)}, \textbf{p90\_ppl\,(.21)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.06) \\
72	GPT-2\,XL, $\tau$  & \textbf{p90\_ppl\,(.25)}, \textbf{p75\,(.15)}, m\_surp\,(.13), var\_surp\,(.12), p50\,(.05) \\
73	GPT-2\,XL, top-$k$ & \textbf{p90\_ppl\,(.24)}, \textbf{p75\,(.12)}, var\_surp\,(.10), m\_surp\,(.09), ttr\,(.04) \\
74	OLMo, nuc.         & \textbf{p90\_ppl\,(.18)}, \textbf{var\_surp\,(.15)}, p75\,(.11), m\_surp\,(.07), ttr\,(.06) \\
75	OLMo, $\tau$       & \textbf{p90\_ppl\,(.21)}, \textbf{var\_surp\,(.16)}, p75\,(.12), m\_surp\,(.09), ttr\,(.05) \\
76	OLMo, top-$k$      & \textbf{p90\_ppl\,(.20)}, \textbf{var\_surp\,(.17)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.05) \\
77	\bottomrule
78	\end{tabular}}
79	\end{table}
80	
81	\begin{figure}[t]
82	\centering
83	\includegraphics[width=\columnwidth]{figures/fig_atlas_heatmap.pdf}
84	\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\S\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}
85	\label{fig:atlas_heatmap}
86	\end{figure}
87	
88	%% ----------------------------------------------------------------
89	\subsection{Monotonicity and Inter-Depth Distances}
90	\label{sec:atlas:monotonicity}
91	
92	Depth features exhibit strong monotonic trends: perplexity tail statistics decrease with depth (Spearman $\rho = -1.0$ across cell-level medians) while repetition features increase (Figure~\ref{fig:feature_trajectory}).
93	Inter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89.
94	
95	% Feature trajectory figure moved to Appendix for space
96	
97	%% ----------------------------------------------------------------
98	\subsection{EDD Analysis}
99	\label{sec:atlas:edd}
100	
101	We extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.
102	Each model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).
103	We train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\ref{eq:edd}.
104	
105	\paragraph{AUC decay and cross-model convergence.}
106	For Pythia-1.4B (nucleus), AUC decays monotonically from $0.999$ (d0v1) to $0.683$ (d4v5); AUC-excess contraction ratios (0.80 at d1v2$\to$d2v3, 0.69 at d3v4$\to$d4v5) show convergence toward indistinguishability accelerates with depth (Figure~\ref{fig:auc_decay}).
107	The d3-vs-d4 AUC clusters near $T{=}0.75$ for all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$.
108	Bootstrap testing ($H_0{:}\, \mathrm{AUC} \leq 0.75$) yields $p = 0.001$ (Pythia), $0.091$ (OLMo), $0.505$ (GPT-2~XL).
109	
110	\paragraph{EDD threshold sensitivity.}
111	Across the 9-cell benchmark (depths 0--3), all cells achieve $\mathrm{EDD}{=}3$ at $T{=}0.65$; at $T{=}0.70$, 8/9 cells; at $T{=}0.75$, 7/9; at $T{=}0.80$, 5/9.
112	Top-$k$ configurations lose $\mathrm{EDD}{=}3$ first (Pythia top-$k$ at $T{=}0.70$, OLMo top-$k$ at $T{=}0.75$); d2-vs-d3 is the consistent bottleneck.
113	
114	\begin{figure}[t]
115	\centering
116	\includegraphics[width=\columnwidth]{figures/fig_auc_decay.pdf}
117	\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \in \{0.65, 0.70, 0.75, 0.80\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\% CIs.}
118	\label{fig:auc_decay}
119	\end{figure}
120	
121	%% ----------------------------------------------------------------
122	\subsection{Strategy-Dependent Trajectories}
123	\label{sec:atlas:strategy}
124	
125	The three strategies induce qualitatively distinct degradation trajectories.
126	Temperature ($\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.9\%, OLMo 82.3\%) because uniform logit scaling accelerates convergence to an attractor~\cite{shumailov2024_nature}, amplifying the fingerprint but creating a boundary reversal risk under cross-strategy transfer (\S\ref{sec:generalization}).
127	Top-$k$ ($k{=}50$) produces the lowest accuracy (68.9--75.8\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens.
128	The strategy effect (9.3\,pp range) exceeds the model effect (7.2\,pp); deployment-time knowledge of the decoding strategy matters at least as much as the generator model.
129	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e87c5788-dd90-4113-9193-da52b894f3d0",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "22ffd09c-bff5-48db-bdc3-aa897b81b0f8",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "content": "\\section{The Depth Degradation Atlas}\n\\label{sec:atlas}\n\nWe present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.\nThe atlas spans $3 \\times 3 = 9$ model--strategy cells evaluated at depths $d \\in \\{0, 1, 2, 3\\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\\S\\ref{sec:atlas:edd}).\n\n%% ----------------------------------------------------------------\n\\subsection{In-Distribution Performance}\n\\label{sec:atlas:id}\n\nTable~\\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.\nAccuracy ranges from 68.9\\% (Pythia, top-$k$) to 85.9\\% (GPT-2~XL, temperature), all exceeding the 25\\% chance baseline by a wide margin.\nTwo axis effects emerge.\nGPT-2~XL achieves the highest accuracy under every strategy (75.8--85.9\\%), followed by OLMo (74.4--82.3\\%) and Pythia (68.9--78.7\\%).\nTop-$k$ sampling yields the lowest accuracy in every model.\nThe mean within-model strategy gap is 9.3~pp, comparable to the 7.2~pp mean within-strategy model gap; decoding strategy and model family contribute roughly equally to performance variance.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Four-class RF accuracy (\\%) with bootstrap 95\\% CI (${\\pm}$half-width; $B{=}1{,}000$). RF with 200 trees, evaluated via 5-fold stratified CV (seed=42). Parenthesized: d1--d3 balanced accuracy from the same 4-class RF (chance = 25\\% / 33\\%). Depth-0 recall exceeds 97\\% in all cells. Within-distribution ordinal quality: MAE\\,=\\,0.23, QWK\\,=\\,0.89 (QWK$_{\\text{d1--d3}}$\\,=\\,0.74); 98.2\\% of errors fall on adjacent depths ($|\\Delta| \\leq 1$).}\n\\label{tab:main_matrix}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n& Nucleus & Temp.\\ $\\tau{=}0.9$ & Top-$k$ \\\\\n\\midrule\nPythia-1.4B  & 78.7{\\scriptsize$\\pm$0.6}\\,(71.8) & 76.8{\\scriptsize$\\pm$0.6}\\,(69.3) & 68.9{\\scriptsize$\\pm$0.6}\\,(58.9) \\\\\nOLMo-1B     & 78.9{\\scriptsize$\\pm$0.6}\\,(72.7) & 82.3{\\scriptsize$\\pm$0.5}\\,(76.6) & 74.4{\\scriptsize$\\pm$0.6}\\,(66.2) \\\\\nGPT-2~XL    & \\textbf{84.3}{\\scriptsize$\\pm$0.5}\\,(79.6) & \\textbf{85.9}{\\scriptsize$\\pm$0.4}\\,(81.5) & \\textbf{75.8}{\\scriptsize$\\pm$0.6}\\,(68.1) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Per-class recall.}\nDepth-0 recall exceeds 97\\% in all 9 cells.\nAmong generated depths, d2 consistently yields the lowest recall (44--73\\%), followed by d3 (61--80\\%) and d1 (72--91\\%).\nThe d2 trough reflects its position at the center of the depth gradient, where features overlap with both d1 and d3, consistent with d2-vs-d3 as the EDD bottleneck (\\S\\ref{sec:atlas:edd}).\nFull per-class recall appears in Appendix~\\ref{app:per_class}.\n\n%% ----------------------------------------------------------------\n\\subsection{Feature Consistency Across the Grid}\n\\label{sec:atlas:features}\n\nDespite the 17.1~pp accuracy spread across cells, a small feature family dominates in every setting.\nPerplexity tail statistics as a feature group dominate depth discrimination: the 90th-percentile perplexity (\\texttt{p90\\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\\texttt{var\\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\\ref{app:permutation}).\\footnote{Individual feature rankings should be interpreted cautiously given high multicollinearity (VIF${>}$10 for 14--16/19 features); the group-level dominance of perplexity tail statistics is robust across importance measures.}\nTable~\\ref{tab:feature_importance} shows the full per-cell ranking.\n\nCross-model feature-rank Spearman correlation averages $\\bar{\\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.\nAmong strategies, top-$k$ yields the highest cross-model rank correlation ($\\rho = 0.811$): the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\\S\\ref{sec:atlas:strategy}).\n\nFeature ablation confirms this concentration: the top-5 features achieve 97.6\\% of full accuracy (76.5\\% vs.\\ 78.4\\%), with perplexity statistics alone reaching 76.6\\% (vs.\\ surprisal 73.2\\%, other categories ${\\leq}$47\\%).\n\nThe feature hierarchy shifts with depth.\nAt shallow boundaries (d1 vs.\\ d2), \\texttt{var\\_surprisal} dominates importance; at deeper boundaries (d3 vs.\\ d4, d4 vs.\\ d5), tail perplexity statistics (\\texttt{p90\\_ppl}, \\texttt{kurtosis\\_ppl}) take over.\nThis transition aligns with model-collapse dynamics~\\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Top-5 features by Gini importance. \\textbf{Bold}: top-2. \\texttt{p90\\_ppl} top-2 in 9/9; \\texttt{var\\_surprisal} 8/9 under SHAP (7/9 under Gini).}\n\\label{tab:feature_importance}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}l l@{}}\n\\toprule\nCell & Top-5 features (Gini importance, ranked) \\\\\n\\midrule\nPythia, nuc.       & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.15)}, m\\_ppl\\,(.11), var\\_ppl\\,(.08), p75\\,(.07) \\\\\nPythia, $\\tau$     & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.14)}, m\\_ppl\\,(.11), p75\\,(.07), m\\_surp\\,(.07) \\\\\nPythia, top-$k$    & \\textbf{var\\_surp\\,(.16)}, \\textbf{p90\\_ppl\\,(.12)}, m\\_ppl\\,(.11), var\\_ppl\\,(.07), m\\_surp\\,(.06) \\\\\nGPT-2\\,XL, nuc.    & \\textbf{var\\_surp\\,(.21)}, \\textbf{p90\\_ppl\\,(.21)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.06) \\\\\nGPT-2\\,XL, $\\tau$  & \\textbf{p90\\_ppl\\,(.25)}, \\textbf{p75\\,(.15)}, m\\_surp\\,(.13), var\\_surp\\,(.12), p50\\,(.05) \\\\\nGPT-2\\,XL, top-$k$ & \\textbf{p90\\_ppl\\,(.24)}, \\textbf{p75\\,(.12)}, var\\_surp\\,(.10), m\\_surp\\,(.09), ttr\\,(.04) \\\\\nOLMo, nuc.         & \\textbf{p90\\_ppl\\,(.18)}, \\textbf{var\\_surp\\,(.15)}, p75\\,(.11), m\\_surp\\,(.07), ttr\\,(.06) \\\\\nOLMo, $\\tau$       & \\textbf{p90\\_ppl\\,(.21)}, \\textbf{var\\_surp\\,(.16)}, p75\\,(.12), m\\_surp\\,(.09), ttr\\,(.05) \\\\\nOLMo, top-$k$      & \\textbf{p90\\_ppl\\,(.20)}, \\textbf{var\\_surp\\,(.17)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.05) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_atlas_heatmap.pdf}\n\\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\\S\\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}\n\\label{fig:atlas_heatmap}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{Monotonicity and Inter-Depth Distances}\n\\label{sec:atlas:monotonicity}\n\nDepth features exhibit strong monotonic trends: perplexity tail statistics decrease with depth (Spearman $\\rho = -1.0$ across cell-level medians) while repetition features increase (Figure~\\ref{fig:feature_trajectory}).\nInter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89.\n\n% Feature trajectory figure moved to Appendix for space\n\n%% ----------------------------------------------------------------\n\\subsection{EDD Analysis}\n\\label{sec:atlas:edd}\n\nWe extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.\nEach model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).\nWe train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\\ref{eq:edd}.\n\n\\paragraph{AUC decay and cross-model convergence.}\nFor Pythia-1.4B (nucleus), AUC decays monotonically from $0.999$ (d0v1) to $0.683$ (d4v5); AUC-excess contraction ratios (0.80 at d1v2$\\to$d2v3, 0.69 at d3v4$\\to$d4v5) show convergence toward indistinguishability accelerates with depth (Figure~\\ref{fig:auc_decay}).\nThe d3-vs-d4 AUC clusters near $T{=}0.75$ for all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$.\nBootstrap testing ($H_0{:}\\, \\mathrm{AUC} \\leq 0.75$) yields $p = 0.001$ (Pythia), $0.091$ (OLMo), $0.505$ (GPT-2~XL).\n\n\\paragraph{EDD threshold sensitivity.}\nAcross the 9-cell benchmark (depths 0--3), all cells achieve $\\mathrm{EDD}{=}3$ at $T{=}0.65$; at $T{=}0.70$, 8/9 cells; at $T{=}0.75$, 7/9; at $T{=}0.80$, 5/9.\nTop-$k$ configurations lose $\\mathrm{EDD}{=}3$ first (Pythia top-$k$ at $T{=}0.70$, OLMo top-$k$ at $T{=}0.75$); d2-vs-d3 is the consistent bottleneck.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_auc_decay.pdf}\n\\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\\% CIs.}\n\\label{fig:auc_decay}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{Strategy-Dependent Trajectories}\n\\label{sec:atlas:strategy}\n\nThe three strategies induce qualitatively distinct degradation trajectories.\nTemperature ($\\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.9\\%, OLMo 82.3\\%) because uniform logit scaling accelerates convergence to an attractor~\\cite{shumailov2024_nature}, amplifying the fingerprint but creating a boundary reversal risk under cross-strategy transfer (\\S\\ref{sec:generalization}).\nTop-$k$ ($k{=}50$) produces the lowest accuracy (68.9--75.8\\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens.\nThe strategy effect (9.3\\,pp range) exceeds the model effect (7.2\\,pp); deployment-time knowledge of the decoding strategy matters at least as much as the generator model.\n",
      "numLines": 129,
      "startLine": 1,
      "totalLines": 129
    }
  },
  "sourceToolAssistantUUID": "e87c5788-dd90-4113-9193-da52b894f3d0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 48 · 2026-05-19T02:59:03.117Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MdTwesJym3RLtAybXd7CBn`</summary>

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
  "parentUuid": "22ffd09c-bff5-48db-bdc3-aa897b81b0f8",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "45dcdece-b825-43fc-b77d-300e1a743c3c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 49 · 2026-05-19T02:59:03.121Z_

<details><summary>↩ Tool result · `toolu_01MdTwesJym3RLtAybXd7CBn`</summary>

```text
1	\section{Generalization and Robustness}
2	\label{sec:generalization}
3	
4	We test whether atlas accuracy (68.9--85.9\%) reflects genuine statistical regularities across eight generalization axes (five below, three in Appendix).
5	
6	\subsection{Classifier Comparison and Surface-Text Ablation}
7	\label{sec:gen:baselines}
8	
9	Table~\ref{tab:baselines} compares ordinal depth estimation methods across all 9 atlas cells.
10	RF, XGBoost, and LightGBM on the same 19 features converge within 0.4\,pp per cell, confirming a feature-determined ceiling; on Pythia nucleus, CORAL \cite{coral2020} (78.1\%) and DivEye \cite{diveye2026} (78.2\%) match RF within 0.6\,pp ($p>0.05$).
11	
12	\paragraph{Binary detectors and membership inference.}
13	Four methods designed for binary AI-text detection or membership inference, when calibrated for ordinal depth, all fall 43--48\,pp below RF (Table~\ref{tab:baselines}).
14	Min-K\% Prob \cite{shi2024_minkprob} (33.2\%) outperforms DetectGPT \cite{mitchell2023_detectgpt} (30.7\%) by 2.5\,pp, consistent with token-level log-probabilities encoding more depth information than perturbation-based curvature; both remain near chance.
15	CORAL ordinal calibration does not close the gap (Min-K\% CORAL d1--d3 BalAcc: 40.4\% vs.\ RF 71.6\%), confirming that the bottleneck is input signal, not calibration.
16	Binary detector scores (Binoculars, Fast-DetectGPT) repurposed as RF features reach 74.2\% on a single cell but average only 30--35\% across 9 cells (Appendix~\ref{app:detector_baselines}).
17	Adding Min-K\% probability as a 20th RF feature yields +0.48\,pp (78.4\%$\to$78.9\%); Min-K\% ranks \#3 by importance (0.095), below \texttt{p90\_ppl} (0.161) and \texttt{var\_surprisal} (0.126), while DetectGPT contributes negligibly (\#17, 0.026).
18	The gain is consistent across 8 of 9 cells but small, confirming that the 19 statistical features already capture the dominant ordinal signal.
19	
20	\paragraph{Surface-text ablation.}
21	Single-feature regression on mean perplexity performs at chance (25.1\%); zero-shot LLMs (DeepSeek V3.2, 36.2\%; Qwen2.5-7B-Instruct, 30.4\%) also fail (43\,pp below the best RF cell; Appendix~\ref{app:zeroshot_prompt}); depth signal resides in distributional statistics inaccessible from surface text.
22	
23	\begin{table}[t]
24	\centering
25	\small
26	\caption{Ordinal depth estimation: method comparison (mean across 9 atlas cells; DetectGPT: 8 of 9, Pythia nucleus excluded due to scoring instability). Chance = 25\% (4-class) / 33.3\% (d1--d3). Min-K\%: $K{=}20$, CORAL calibration. DetectGPT: gpt2-large scoring, t5-large perturbation ($n{=}5$). 5-fold CV; SD $\leq$ 0.9\,pp for feature-based methods.}
27	\label{tab:baselines}
28	\resizebox{\columnwidth}{!}{%
29	\begin{tabular}{@{}lcc@{}}
30	\toprule
31	Method & 4-Cl Acc (\%) & d1--d3 BalAcc (\%) \\
32	\midrule
33	RF 19-feature (ours) & \textbf{78.4} & \textbf{71.6} \\
34	\midrule
35	Zero-shot LLM (best) & 36.2 & --- \\
36	Min-K\% Prob (CORAL) & 33.2 & 40.4 \\
37	DetectGPT (perturbation) & 30.7 & 24.3 \\
38	Random & 25.0 & 33.3 \\
39	\bottomrule
40	\end{tabular}}
41	\end{table}
42	
43	Convergence confirms the signal resides in the features (three classifiers match within 0.8\,pp under cross-model transfer; Appendix~\ref{app:learned_estimator}).
44	Perplexity features alone recover 66.0\% ($-$0.5\,pp vs.\ full), while repetition/diversity features alone fall 13.6\,pp below; perplexity degradation is the dominant depth marker.
45	Raw perplexity alone performs at chance (25.1\%); the strongest single feature (\texttt{p90\_ppl}) reaches 58.3\% ($-$8.3\,pp vs.\ full); multi-dimensional characterization is required. Figure~\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread to d1--d3 under transfer (RF seed std $= 0.06$\,pp; Appendix~\ref{app:rf_seed}).
46	Cross-seed replication across all three model families confirms consistent feature rankings and depth ordering; absolute accuracy varies by $+$0.1 to $+$3.2\,pp (same direction), with 2/3 deltas statistically significant (Appendix~\ref{app:seed_replication}).
47	
48	\begin{figure}[t]
49	\centering
50	\includegraphics[width=\columnwidth]{figures/fig_confusion_matrix.pdf}
51	\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\tau{=}0.9$, 85.9\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\%). d0 recall exceeds 99\% in both; errors spread across the d1--d3 range under transfer.}
52	\label{fig:confusion_matrix}
53	\end{figure}
54	
55	\subsection{Cross-Model Transfer}
56	\label{sec:gen:crossmodel}
57	
58	We perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\ref{tab:cross_model}).
59	
60	\begin{table}[t]
61	\centering
62	\small
63	\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\% / 33\% (d1--d3). d1--d3 bal.\ acc: Pythia 49.9\%, OLMo 59.2\%, GPT-2~XL 57.2\% (mean 55.4\%). Ordinal quality: MAE\,=\,0.39, QWK\,=\,0.81 (QWK$_{\text{d1--d3}}$\,=\,0.53); 94.8\% of errors at $|\Delta| \leq 1$.}
64	\label{tab:cross_model}
65	\begin{tabular}{lccccc}
66	\toprule
67	Holdout & Acc & d0 & d1 & d2 & d3 \\
68	 & (\%) & Rec. & Rec. & Rec. & Rec. \\
69	\midrule
70	Pythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\
71	OLMo & \textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\
72	GPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\
73	\midrule
74	Mean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\
75	\bottomrule
76	\end{tabular}
77	\end{table}
78	
79	Mean transfer accuracy is 66.4\% (2.7$\times$ chance); d0 recall ($>$98\%) inflates the headline (d1--d3 balanced mean 55.4\%).
80	
81	\subsection{Cross-Strategy Transfer}
82	\label{sec:gen:crossstrategy}
83	
84	Table~\ref{tab:cross_strategy} reports leave-one-strategy-out transfer.
85	
86	\begin{table}[t]
87	\centering
88	\small
89	\caption{Cross-strategy transfer (leave-one-out). Chance = 25\% / 33\% (d1--d3). d0 recall $\geq$89\% inflates headline; d1--d3 mean: 45.9\%.}
90	\label{tab:cross_strategy}
91	\begin{tabular}{lccc}
92	\toprule
93	Holdout & Pythia & OLMo & GPT-2 XL \\
94	 & Acc (\%) & Acc (\%) & Acc (\%) \\
95	\midrule
96	nucleus & \textbf{69.4} & \textbf{65.4} & \textbf{59.9} \\
97	temp ($\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\
98	top-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\
99	\bottomrule
100	\end{tabular}
101	\end{table}
102	
103	Mean cross-strategy accuracy (59.1\%) falls 7\,pp below cross-model transfer; d1--d3 accuracy drops to 45.9\% (chance = 33\%).
104	Training on nucleus + top-$k$ inverts the d1/d2 boundary under temperature (d1v2 AUC $<$ 0.5), because temperature scaling accelerates convergence (\S\ref{sec:method:theory}); strategy confusion concentrates between temperature and top-$k$ (31.2\%).
105	A two-stage pipeline (strategy identification + depth classification) recovers 11.5\,pp; conditional decomposition shows a 31.5\,pp d1--d3 gap between correct and wrong routing, confirming feature-space misalignment rather than uniform noise (Appendix~\ref{app:extended_discussion}).
106	
107	\paragraph{Prompted generation.}
108	Replicating the GPT-2~XL nucleus pipeline with topic-seeded generation yields 69.5\% (95\% CI $[68.9, 70.2]$, $-$13.8\,pp vs.\ BOS-seeded, $2.8\times$ chance), with monotonic AUC decay and identical top features (Appendix~\ref{app:prompted_gen}): prompt conditioning attenuates but does not eliminate the depth signal.
109	
110	%% ----------------------------------------------------------------
111	\subsection{Preliminary Cross-Scale Observations}
112	\label{sec:gen:crossscale}
113	
114	At 7--8B scale (QLoRA), Llama-3.1-8B \cite{llama3} achieves 70.2\% ($\mathrm{EDD}_{0.70}{=}4$) and Qwen2.5-7B \cite{qwen2.5} 60.1\%; at 14B (Qwen2.5-14B, self-reference model), accuracy drops to 54.1\% ($\mathrm{EDD}_{0.70}{=}0$), though d1--d3 balanced accuracy (57.4\%) exceeds chance (33\%).
115	These results are confounded by quantization, sample size, and reference model differences (Appendix~\ref{app:cross_scale_confounds}); a base-model control suggests instruction tuning regularizes degradation (Appendix~\ref{app:instruct_1p5b}).
116	Cross-model chains (84.75\%), cross-domain arXiv (74.1\%), and LoRA rank sensitivity ($\Delta{=}4.65$\,pp) further confirm robustness (Appendix~\ref{app:cross_scale_full}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "45dcdece-b825-43fc-b77d-300e1a743c3c",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "b43df74d-7b25-4cd5-bd21-1f027ed939ad",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
      "content": "\\section{Generalization and Robustness}\n\\label{sec:generalization}\n\nWe test whether atlas accuracy (68.9--85.9\\%) reflects genuine statistical regularities across eight generalization axes (five below, three in Appendix).\n\n\\subsection{Classifier Comparison and Surface-Text Ablation}\n\\label{sec:gen:baselines}\n\nTable~\\ref{tab:baselines} compares ordinal depth estimation methods across all 9 atlas cells.\nRF, XGBoost, and LightGBM on the same 19 features converge within 0.4\\,pp per cell, confirming a feature-determined ceiling; on Pythia nucleus, CORAL \\cite{coral2020} (78.1\\%) and DivEye \\cite{diveye2026} (78.2\\%) match RF within 0.6\\,pp ($p>0.05$).\n\n\\paragraph{Binary detectors and membership inference.}\nFour methods designed for binary AI-text detection or membership inference, when calibrated for ordinal depth, all fall 43--48\\,pp below RF (Table~\\ref{tab:baselines}).\nMin-K\\% Prob \\cite{shi2024_minkprob} (33.2\\%) outperforms DetectGPT \\cite{mitchell2023_detectgpt} (30.7\\%) by 2.5\\,pp, consistent with token-level log-probabilities encoding more depth information than perturbation-based curvature; both remain near chance.\nCORAL ordinal calibration does not close the gap (Min-K\\% CORAL d1--d3 BalAcc: 40.4\\% vs.\\ RF 71.6\\%), confirming that the bottleneck is input signal, not calibration.\nBinary detector scores (Binoculars, Fast-DetectGPT) repurposed as RF features reach 74.2\\% on a single cell but average only 30--35\\% across 9 cells (Appendix~\\ref{app:detector_baselines}).\nAdding Min-K\\% probability as a 20th RF feature yields +0.48\\,pp (78.4\\%$\\to$78.9\\%); Min-K\\% ranks \\#3 by importance (0.095), below \\texttt{p90\\_ppl} (0.161) and \\texttt{var\\_surprisal} (0.126), while DetectGPT contributes negligibly (\\#17, 0.026).\nThe gain is consistent across 8 of 9 cells but small, confirming that the 19 statistical features already capture the dominant ordinal signal.\n\n\\paragraph{Surface-text ablation.}\nSingle-feature regression on mean perplexity performs at chance (25.1\\%); zero-shot LLMs (DeepSeek V3.2, 36.2\\%; Qwen2.5-7B-Instruct, 30.4\\%) also fail (43\\,pp below the best RF cell; Appendix~\\ref{app:zeroshot_prompt}); depth signal resides in distributional statistics inaccessible from surface text.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Ordinal depth estimation: method comparison (mean across 9 atlas cells; DetectGPT: 8 of 9, Pythia nucleus excluded due to scoring instability). Chance = 25\\% (4-class) / 33.3\\% (d1--d3). Min-K\\%: $K{=}20$, CORAL calibration. DetectGPT: gpt2-large scoring, t5-large perturbation ($n{=}5$). 5-fold CV; SD $\\leq$ 0.9\\,pp for feature-based methods.}\n\\label{tab:baselines}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nMethod & 4-Cl Acc (\\%) & d1--d3 BalAcc (\\%) \\\\\n\\midrule\nRF 19-feature (ours) & \\textbf{78.4} & \\textbf{71.6} \\\\\n\\midrule\nZero-shot LLM (best) & 36.2 & --- \\\\\nMin-K\\% Prob (CORAL) & 33.2 & 40.4 \\\\\nDetectGPT (perturbation) & 30.7 & 24.3 \\\\\nRandom & 25.0 & 33.3 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nConvergence confirms the signal resides in the features (three classifiers match within 0.8\\,pp under cross-model transfer; Appendix~\\ref{app:learned_estimator}).\nPerplexity features alone recover 66.0\\% ($-$0.5\\,pp vs.\\ full), while repetition/diversity features alone fall 13.6\\,pp below; perplexity degradation is the dominant depth marker.\nRaw perplexity alone performs at chance (25.1\\%); the strongest single feature (\\texttt{p90\\_ppl}) reaches 58.3\\% ($-$8.3\\,pp vs.\\ full); multi-dimensional characterization is required. Figure~\\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread to d1--d3 under transfer (RF seed std $= 0.06$\\,pp; Appendix~\\ref{app:rf_seed}).\nCross-seed replication across all three model families confirms consistent feature rankings and depth ordering; absolute accuracy varies by $+$0.1 to $+$3.2\\,pp (same direction), with 2/3 deltas statistically significant (Appendix~\\ref{app:seed_replication}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_confusion_matrix.pdf}\n\\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\\tau{=}0.9$, 85.9\\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\\%). d0 recall exceeds 99\\% in both; errors spread across the d1--d3 range under transfer.}\n\\label{fig:confusion_matrix}\n\\end{figure}\n\n\\subsection{Cross-Model Transfer}\n\\label{sec:gen:crossmodel}\n\nWe perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\\ref{tab:cross_model}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\\% / 33\\% (d1--d3). d1--d3 bal.\\ acc: Pythia 49.9\\%, OLMo 59.2\\%, GPT-2~XL 57.2\\% (mean 55.4\\%). Ordinal quality: MAE\\,=\\,0.39, QWK\\,=\\,0.81 (QWK$_{\\text{d1--d3}}$\\,=\\,0.53); 94.8\\% of errors at $|\\Delta| \\leq 1$.}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nHoldout & Acc & d0 & d1 & d2 & d3 \\\\\n & (\\%) & Rec. & Rec. & Rec. & Rec. \\\\\n\\midrule\nPythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\\\\nOLMo & \\textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\\\\nGPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\\\\n\\midrule\nMean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean transfer accuracy is 66.4\\% (2.7$\\times$ chance); d0 recall ($>$98\\%) inflates the headline (d1--d3 balanced mean 55.4\\%).\n\n\\subsection{Cross-Strategy Transfer}\n\\label{sec:gen:crossstrategy}\n\nTable~\\ref{tab:cross_strategy} reports leave-one-strategy-out transfer.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-strategy transfer (leave-one-out). Chance = 25\\% / 33\\% (d1--d3). d0 recall $\\geq$89\\% inflates headline; d1--d3 mean: 45.9\\%.}\n\\label{tab:cross_strategy}\n\\begin{tabular}{lccc}\n\\toprule\nHoldout & Pythia & OLMo & GPT-2 XL \\\\\n & Acc (\\%) & Acc (\\%) & Acc (\\%) \\\\\n\\midrule\nnucleus & \\textbf{69.4} & \\textbf{65.4} & \\textbf{59.9} \\\\\ntemp ($\\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\\\\ntop-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean cross-strategy accuracy (59.1\\%) falls 7\\,pp below cross-model transfer; d1--d3 accuracy drops to 45.9\\% (chance = 33\\%).\nTraining on nucleus + top-$k$ inverts the d1/d2 boundary under temperature (d1v2 AUC $<$ 0.5), because temperature scaling accelerates convergence (\\S\\ref{sec:method:theory}); strategy confusion concentrates between temperature and top-$k$ (31.2\\%).\nA two-stage pipeline (strategy identification + depth classification) recovers 11.5\\,pp; conditional decomposition shows a 31.5\\,pp d1--d3 gap between correct and wrong routing, confirming feature-space misalignment rather than uniform noise (Appendix~\\ref{app:extended_discussion}).\n\n\\paragraph{Prompted generation.}\nReplicating the GPT-2~XL nucleus pipeline with topic-seeded generation yields 69.5\\% (95\\% CI $[68.9, 70.2]$, $-$13.8\\,pp vs.\\ BOS-seeded, $2.8\\times$ chance), with monotonic AUC decay and identical top features (Appendix~\\ref{app:prompted_gen}): prompt conditioning attenuates but does not eliminate the depth signal.\n\n%% ----------------------------------------------------------------\n\\subsection{Preliminary Cross-Scale Observations}\n\\label{sec:gen:crossscale}\n\nAt 7--8B scale (QLoRA), Llama-3.1-8B \\cite{llama3} achieves 70.2\\% ($\\mathrm{EDD}_{0.70}{=}4$) and Qwen2.5-7B \\cite{qwen2.5} 60.1\\%; at 14B (Qwen2.5-14B, self-reference model), accuracy drops to 54.1\\% ($\\mathrm{EDD}_{0.70}{=}0$), though d1--d3 balanced accuracy (57.4\\%) exceeds chance (33\\%).\nThese results are confounded by quantization, sample size, and reference model differences (Appendix~\\ref{app:cross_scale_confounds}); a base-model control suggests instruction tuning regularizes degradation (Appendix~\\ref{app:instruct_1p5b}).\nCross-model chains (84.75\\%), cross-domain arXiv (74.1\\%), and LoRA rank sensitivity ($\\Delta{=}4.65$\\,pp) further confirm robustness (Appendix~\\ref{app:cross_scale_full}).",
      "numLines": 116,
      "startLine": 1,
      "totalLines": 116
    }
  },
  "sourceToolAssistantUUID": "45dcdece-b825-43fc-b77d-300e1a743c3c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 50 · 2026-05-19T02:59:03.573Z_

<details open><summary>🔧 Tool call — Read · `toolu_017uUvgYs2zna8yEGdNJTFFo`</summary>

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
  "parentUuid": "b43df74d-7b25-4cd5-bd21-1f027ed939ad",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "f49742d1-65d4-4050-b775-a3672dffbf76",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 51 · 2026-05-19T02:59:03.577Z_

<details><summary>↩ Tool result · `toolu_017uUvgYs2zna8yEGdNJTFFo`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	
4	This paper formalizes recursive generation depth estimation as ordinal classification.
5	Perplexity tail statistics (\texttt{p90\_ppl}, \texttt{var\_surprisal}) are consistent depth markers across all nine model--strategy cells; five features retain 97.6\% of full performance, and $\mathrm{EDD}_{0.70}{=}4$ for all three families (confirmed by 5-class extension, 71--80\%; Appendix~\ref{app:depth4_ext}).
6	Cross-model transfer reaches 66.4\% ($2.7\times$ chance), cross-model chains 84.75\%, and cross-domain arXiv 74.1\%; binary detectors and membership inference methods achieve only 30--35\%, confirming that depth-specific distributional features are necessary.
7	Cross-strategy transfer remains the primary bottleneck (d1--d3: 45.9\%); scale-dependent signal attenuation, depth-quality entanglement, and cross-strategy deployment are open challenges (Appendix~\ref{app:extended_discussion}).
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f49742d1-65d4-4050-b775-a3672dffbf76",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "ccf80e3a-dcec-40cf-922e-639b541a172e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nThis paper formalizes recursive generation depth estimation as ordinal classification.\nPerplexity tail statistics (\\texttt{p90\\_ppl}, \\texttt{var\\_surprisal}) are consistent depth markers across all nine model--strategy cells; five features retain 97.6\\% of full performance, and $\\mathrm{EDD}_{0.70}{=}4$ for all three families (confirmed by 5-class extension, 71--80\\%; Appendix~\\ref{app:depth4_ext}).\nCross-model transfer reaches 66.4\\% ($2.7\\times$ chance), cross-model chains 84.75\\%, and cross-domain arXiv 74.1\\%; binary detectors and membership inference methods achieve only 30--35\\%, confirming that depth-specific distributional features are necessary.\nCross-strategy transfer remains the primary bottleneck (d1--d3: 45.9\\%); scale-dependent signal attenuation, depth-quality entanglement, and cross-strategy deployment are open challenges (Appendix~\\ref{app:extended_discussion}).\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "f49742d1-65d4-4050-b775-a3672dffbf76",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-19T02:59:04.045Z_

<details open><summary>🔧 Tool call — Read · `toolu_018eKiUCNkaZmzkQNdp7aQBg`</summary>

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
  "parentUuid": "ccf80e3a-dcec-40cf-922e-639b541a172e",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "f75cea36-decf-4497-9f36-c8627bc5283a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 53 · 2026-05-19T02:59:04.053Z_

<details><summary>↩ Tool result · `toolu_018eKiUCNkaZmzkQNdp7aQBg`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	\paragraph{Cross-strategy deployment constraint.}
5	Cross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.
6	Per-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\to}0.56$, OLMo $0.19{\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\Delta < 0.02$\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\sim}0.83$); a two-stage pipeline (strategy identification + strategy-conditioned classification) is therefore needed for reliable cross-strategy deployment.
7	
8	\paragraph{Strategy-unknown deployment.}
9	In strategy-unknown settings, naive transfer on d1--d3 yields only 45.9\%, and d1/d2 predictions may invert.
10	A two-stage pipeline recovers 11.5\,pp over LOO, though per-model gains vary (GPT-2~XL $+$16.4\,pp vs.\ Pythia $+$8.0\,pp).
11	Practical deployment requires either strategy metadata or learned routing.
12	
13	\paragraph{d0 inflation of headline metrics.}
14	Depth~0 (human-written text) is near-perfectly separable (recall $>$97\% across all nine model--strategy settings), inflating headline accuracy.
15	Cross-model transfer accuracy of 66.4\% is substantially driven by d0; d2 recall drops to 26.8\% in the worst case (Pythia holdout).
16	
17	\paragraph{Controlled vs.\ ecological setting.}
18	The primary benchmark uses Wikipedia seed text with controlled LoRA fine-tuning (1--1.5B models), a design that isolates the depth variable but diverges from wild contamination where models train on mixed corpora with prior-generation outputs at unknown proportions.
19	Domain bias controls confirm depth as the dominant factor: LOGO accuracy (72.1\%) matches standard CV (72.0\%), seed-group prediction is at chance (10.2\%; Appendix~\ref{app:domain_bias}).
20	Cross-scale experiments (7--14B, \S\ref{sec:gen:crossscale}) show signal that attenuates with scale; at 14B, d0/d1 separability nearly vanishes ($\mathrm{EDD}_{0.70}{=}0$) while d1--d3 discrimination persists; this constitutes a boundary condition for the current feature set (confounded by self-reference model; Appendix~\ref{app:cross_scale_confounds}).
21	A base-model control suggests instruction-tuning regularizes degradation.
22	Segment-level estimation in mixed-depth documents remains open (Appendix~\ref{app:mixed_depth}); in particular, partial mixing (accumulation), where a single document contains fragments from different recursive depths, is a key open question, as our framework assumes uniform depth per passage.
23	
24	\paragraph{Domain-dependent false positive rate.}
25	On editorial text (WikiText-103), all classifiers achieve $\geq$98.5\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), per-model FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL).
26	A pooled RF classifier evaluated on larger corpora (10{,}000 passages each) yields 34\% FPR on C4 and 17\% on FineWeb \cite{penedo2024_fineweb}; the gap reflects quality filtering in FineWeb removing feature-anomalous text that triggers false positives.
27	Misclassifications concentrate in template/SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0).
28	Confidence thresholding ($P(\mathrm{d0}) \geq 0.15$) reduces pooled FPR from 34\%/17\% to 2.8\%/0.7\% on C4/FineWeb at minimal accuracy cost ($-$0.3\,pp); high FPR is therefore a decision-threshold problem, not a fundamental calibration defect, though the optimal threshold remains domain-dependent (Appendix~\ref{app:calibration}).
29	
30	\paragraph{Adversarial robustness.}
31	Adversarial paraphrasing \cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.
32	
33	\paragraph{EDD monotonicity assumption.}
34	Our EDD definition (Eq.~\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically, as observed in all our configurations.
35	However, \citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).
36	Our cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.
37	In such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.
38	The choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.
39	
40	\paragraph{Reference model dependency.}
41	Reference model choice affects classification accuracy by up to 11\,pp; same-family references yield optimal performance, though all configurations exceed $2.5\times$ chance.
42	Surprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.
43	For the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.
44	Empirically, the self-model configuration does not yield the highest accuracy (Pythia 78.7\% vs.\ GPT-2~XL 85.9\%); the overlap therefore does not confer a systematic advantage.
45	An ablation with OLMo-1B and GPT-2 XL as alternative references shows accuracy ranging from 67--79\% across three reference architectures (Appendix~\ref{app:ref_ablation}), all exceeding $2.5\times$ chance; same-family reference yields optimal performance ($\Delta{\leq}$11\,pp).
46	The choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.
47	Reference-free surface features alone achieve 53.7\% (partial signal in lexical statistics) but trail the full pipeline by 25pp; surprisal-based features are therefore essential.
48	Simple multi-reference ensembling does not outperform the best single reference (73.7\% vs.\ 78.6\%).
49	
50	\paragraph{Single LoRA instance.}
51	Cross-seed replication covers 3 of 9 cells (Pythia, OLMo, GPT-2~XL nucleus); seed=43 yields $+$0.1 to $+$3.2\,pp higher accuracy, with 2/3 deltas statistically significant (non-overlapping CIs).
52	Feature rankings and depth ordering are consistent across seeds, but single-seed absolute accuracy carries ${\sim}$1--3\,pp uncertainty; cross-cell comparisons should be interpreted cautiously.
53	
54	\paragraph{Additional caveats.}
55	Depth signal scales with passage length (68.4\% at 128 tokens, 77.8\% at 512; Appendix~\ref{app:length_ablation}), saturating near 500 tokens.
56	Prompted generation was validated on only 1 of 9 cells (GPT-2~XL nucleus); generalization to other model--strategy configurations under prompted conditions is not established.
57	Detection features degrade under domain shift \cite{pudasaini2026_detection_fails}, and curated synthetic data may not trigger collapse \cite{falahati2026_curated}, attenuating the fingerprints we exploit.
58	
59	\section*{Ethics Statement}
60	
61	This work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.
62	No human subjects were involved, no private or sensitive data were collected, and no new models were released.
63	Our method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.
64	Code and data will be released upon acceptance.
65	This research used AI coding assistants for experiment implementation and writing drafts.
66	All scientific decisions, experimental design, and result interpretation were conducted by the authors.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f75cea36-decf-4497-9f36-c8627bc5283a",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "35659f48-39b7-4f7d-b88e-6d401aacb6a8",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\n\\paragraph{Cross-strategy deployment constraint.}\nCross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.\nPer-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\\to}0.56$, OLMo $0.19{\\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\\Delta < 0.02$\\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\\sim}0.83$); a two-stage pipeline (strategy identification + strategy-conditioned classification) is therefore needed for reliable cross-strategy deployment.\n\n\\paragraph{Strategy-unknown deployment.}\nIn strategy-unknown settings, naive transfer on d1--d3 yields only 45.9\\%, and d1/d2 predictions may invert.\nA two-stage pipeline recovers 11.5\\,pp over LOO, though per-model gains vary (GPT-2~XL $+$16.4\\,pp vs.\\ Pythia $+$8.0\\,pp).\nPractical deployment requires either strategy metadata or learned routing.\n\n\\paragraph{d0 inflation of headline metrics.}\nDepth~0 (human-written text) is near-perfectly separable (recall $>$97\\% across all nine model--strategy settings), inflating headline accuracy.\nCross-model transfer accuracy of 66.4\\% is substantially driven by d0; d2 recall drops to 26.8\\% in the worst case (Pythia holdout).\n\n\\paragraph{Controlled vs.\\ ecological setting.}\nThe primary benchmark uses Wikipedia seed text with controlled LoRA fine-tuning (1--1.5B models), a design that isolates the depth variable but diverges from wild contamination where models train on mixed corpora with prior-generation outputs at unknown proportions.\nDomain bias controls confirm depth as the dominant factor: LOGO accuracy (72.1\\%) matches standard CV (72.0\\%), seed-group prediction is at chance (10.2\\%; Appendix~\\ref{app:domain_bias}).\nCross-scale experiments (7--14B, \\S\\ref{sec:gen:crossscale}) show signal that attenuates with scale; at 14B, d0/d1 separability nearly vanishes ($\\mathrm{EDD}_{0.70}{=}0$) while d1--d3 discrimination persists; this constitutes a boundary condition for the current feature set (confounded by self-reference model; Appendix~\\ref{app:cross_scale_confounds}).\nA base-model control suggests instruction-tuning regularizes degradation.\nSegment-level estimation in mixed-depth documents remains open (Appendix~\\ref{app:mixed_depth}); in particular, partial mixing (accumulation), where a single document contains fragments from different recursive depths, is a key open question, as our framework assumes uniform depth per passage.\n\n\\paragraph{Domain-dependent false positive rate.}\nOn editorial text (WikiText-103), all classifiers achieve $\\geq$98.5\\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), per-model FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL).\nA pooled RF classifier evaluated on larger corpora (10{,}000 passages each) yields 34\\% FPR on C4 and 17\\% on FineWeb \\cite{penedo2024_fineweb}; the gap reflects quality filtering in FineWeb removing feature-anomalous text that triggers false positives.\nMisclassifications concentrate in template/SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0).\nConfidence thresholding ($P(\\mathrm{d0}) \\geq 0.15$) reduces pooled FPR from 34\\%/17\\% to 2.8\\%/0.7\\% on C4/FineWeb at minimal accuracy cost ($-$0.3\\,pp); high FPR is therefore a decision-threshold problem, not a fundamental calibration defect, though the optimal threshold remains domain-dependent (Appendix~\\ref{app:calibration}).\n\n\\paragraph{Adversarial robustness.}\nAdversarial paraphrasing \\cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.\n\n\\paragraph{EDD monotonicity assumption.}\nOur EDD definition (Eq.~\\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically, as observed in all our configurations.\nHowever, \\citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \\emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).\nOur cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.\nIn such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.\nThe choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.\n\n\\paragraph{Reference model dependency.}\nReference model choice affects classification accuracy by up to 11\\,pp; same-family references yield optimal performance, though all configurations exceed $2.5\\times$ chance.\nSurprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.\nFor the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.\nEmpirically, the self-model configuration does not yield the highest accuracy (Pythia 78.7\\% vs.\\ GPT-2~XL 85.9\\%); the overlap therefore does not confer a systematic advantage.\nAn ablation with OLMo-1B and GPT-2 XL as alternative references shows accuracy ranging from 67--79\\% across three reference architectures (Appendix~\\ref{app:ref_ablation}), all exceeding $2.5\\times$ chance; same-family reference yields optimal performance ($\\Delta{\\leq}$11\\,pp).\nThe choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.\nReference-free surface features alone achieve 53.7\\% (partial signal in lexical statistics) but trail the full pipeline by 25pp; surprisal-based features are therefore essential.\nSimple multi-reference ensembling does not outperform the best single reference (73.7\\% vs.\\ 78.6\\%).\n\n\\paragraph{Single LoRA instance.}\nCross-seed replication covers 3 of 9 cells (Pythia, OLMo, GPT-2~XL nucleus); seed=43 yields $+$0.1 to $+$3.2\\,pp higher accuracy, with 2/3 deltas statistically significant (non-overlapping CIs).\nFeature rankings and depth ordering are consistent across seeds, but single-seed absolute accuracy carries ${\\sim}$1--3\\,pp uncertainty; cross-cell comparisons should be interpreted cautiously.\n\n\\paragraph{Additional caveats.}\nDepth signal scales with passage length (68.4\\% at 128 tokens, 77.8\\% at 512; Appendix~\\ref{app:length_ablation}), saturating near 500 tokens.\nPrompted generation was validated on only 1 of 9 cells (GPT-2~XL nucleus); generalization to other model--strategy configurations under prompted conditions is not established.\nDetection features degrade under domain shift \\cite{pudasaini2026_detection_fails}, and curated synthetic data may not trigger collapse \\cite{falahati2026_curated}, attenuating the fingerprints we exploit.\n\n\\section*{Ethics Statement}\n\nThis work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.\nNo human subjects were involved, no private or sensitive data were collected, and no new models were released.\nOur method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.\nCode and data will be released upon acceptance.\nThis research used AI coding assistants for experiment implementation and writing drafts.\nAll scientific decisions, experimental design, and result interpretation were conducted by the authors.",
      "numLines": 66,
      "startLine": 1,
      "totalLines": 66
    }
  },
  "sourceToolAssistantUUID": "f75cea36-decf-4497-9f36-c8627bc5283a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-19T02:59:04.519Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MXGcdFPoTqam3WF72EVhbH`</summary>

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
  "parentUuid": "35659f48-39b7-4f7d-b88e-6d401aacb6a8",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "b37c39a3-a88d-435f-8238-19ed2ce96ebd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 55 · 2026-05-19T02:59:04.872Z_

<details><summary>↩ Tool result · `toolu_01MXGcdFPoTqam3WF72EVhbH`</summary>

```text
1	\section{LoRA Fine-Tuning Protocol}
2	\label{app:lora_protocol}
3	
4	Table~\ref{tab:lora_protocol} lists the full LoRA fine-tuning configuration used for recursive chain construction (\S\ref{sec:method:benchmark}).
5	At each depth $k$, a fresh LoRA adapter is initialized on the base model and trained on $\mathcal{D}_{k-1}$; adapters are not inherited across depths.
6	The HuggingFace Trainer default linear decay schedule is used with no warmup.
7	Target modules are model-specific: \texttt{query\_key\_value} (Pythia), \texttt{att\_proj} (OLMo), and \texttt{c\_attn} (GPT-2~XL).
8	Cross-scale experiments (\S\ref{sec:gen:crossscale}) use QLoRA (4-bit NF4) with $r{=}16$, $\alpha{=}32$.
9	
10	\begin{table}[h]
11	\centering
12	\small
13	\caption{LoRA fine-tuning hyperparameters for the primary 1--1.5B benchmark. Identical across all three model families and all depth levels.}
14	\label{tab:lora_protocol}
15	\begin{tabular}{@{}ll@{}}
16	\toprule
17	Parameter & Value \\
18	\midrule
19	LoRA rank $r$ & 16 \\
20	LoRA alpha $\alpha$ & 32 \\
21	LoRA dropout & 0.05 \\
22	Bias & none \\
23	Epochs per depth & 3 \\
24	Learning rate & $2 \times 10^{-4}$ \\
25	LR schedule & linear decay (no warmup) \\
26	Batch size (effective) & 16 ($8 \times 2$ grad.\ accum.) \\
27	Max sequence length & 512 tokens \\
28	Precision & bfloat16 \\
29	Adapter init & from scratch (base model) \\
30	Seed & 42 (primary), 43 (replication) \\
31	\bottomrule
32	\end{tabular}
33	\end{table}
34	
35	\section{Additional Results}
36	\label{app:additional}
37	
38	\subsection{Top-$k$ Feature Trajectories}
39	\label{app:topk_trajectories}
40	
41	Figure~\ref{fig:feature_trajectory} shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\tau{=}0.9$) sampling.
42	Top-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \S\ref{sec:atlas:strategy}.
43	Concretely, the d0$\to$d1 drop in \texttt{p90\_ppl} under top-$k$ is 78\% (vs.\ 87\% for nucleus), and the d2$\to$d3 reduction is 31\% (vs.\ 39\% for nucleus).
44	Despite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.
45	
46	\subsection{Permutation Importance}
47	\label{app:permutation}
48	
49	To verify that the Gini-based importance rankings in \S\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.
50	The top-2 features are stable across measures: \texttt{p90\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \texttt{var\_surprisal} in 8/9 (vs.\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \texttt{p75\_ppl} displaces \texttt{var\_surprisal} to rank 3).
51	Kendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).
52	Pairwise Spearman correlations are: SHAP--Gini $\rho{=}0.93$, SHAP--permutation $\rho{=}0.84$, Gini--permutation $\rho{=}0.76$.
53	Per-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical; the top features are therefore robust to the choice of importance measure at the aggregate level, though per-cell rankings exhibit model-dependent variation.
54	
55	\subsection{Feature Trajectories}
56	\label{app:feature_trajectories}
57	
58	\begin{figure}[h]
59	\centering
60	\includegraphics[width=\columnwidth]{figures/fig_feature_trajectory.pdf}
61	\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \texttt{p90\_ppl} (monotonically decreasing). Middle: \texttt{var\_surprisal} (decreasing). Bottom: \texttt{rep\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \to d{=}1$ gap exceeds all subsequent inter-depth gaps.}
62	\label{fig:feature_trajectory}
63	\end{figure}
64	
65	\subsection{Per-Class Recall}
66	\label{app:per_class}
67	
68	Table~\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).
69	Depth~0 recall exceeds 97\% uniformly.
70	Among generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.
71	
72	\begin{table}[h]
73	\centering
74	\small
75	\caption{Per-class recall (\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}
76	\label{tab:per_class_recall}
77	\begin{tabular}{@{}lcccc@{}}
78	\toprule
79	Cell & d0 & d1 & d2 & d3 \\
80	\midrule
81	Pythia, nuc.       & 99.3 & 81.9 & 59.2 & 74.4 \\
82	Pythia, $\tau$     & 99.2 & 79.9 & 56.0 & 72.1 \\
83	Pythia, top-$k$    & 98.7 & 71.6 & 44.2 & 60.9 \\
84	OLMo, nuc.         & 97.8 & 82.1 & 60.6 & 75.3 \\
85	OLMo, $\tau$       & 99.3 & 87.1 & 65.6 & 77.1 \\
86	OLMo, top-$k$      & 99.2 & 80.9 & 50.4 & 67.2 \\
87	GPT-2~XL, nuc.     & 98.5 & 87.4 & 72.8 & 78.5 \\
88	GPT-2~XL, $\tau$   & 99.0 & 91.1 & \textbf{73.0} & 80.5 \\
89	GPT-2~XL, top-$k$  & 98.7 & 81.3 & 54.8 & 68.4 \\
90	\bottomrule
91	\end{tabular}
92	\end{table}
93	
94	\subsection{DCOL Iteration Details}
95	\label{app:dcol_iterations}
96	
97	Table~\ref{tab:dcol_iterations} summarizes all six DCOL iterations.
98	DeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.
99	
100	\begin{table}[h]
101	\centering
102	\small
103	\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.7\%.}
104	\label{tab:dcol_iterations}
105	\resizebox{\columnwidth}{!}{%
106	\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}
107	\toprule
108	Ver. & Backbone & Config & Outcome \\
109	\midrule
110	v1 & DeBERTa & FT, m\_lr $10^{-3}$ & Embed.\ collapse (31.5\%) \\
111	v2 & DeBERTa & FT, m\_lr $10^{-4}$ & OOM \\
112	v3 & DeBERTa & FT, m\_lr $10^{-4}$ & Forgetting + OOM \\
113	v4 & DeBERTa & LoRA, m\_lr $10^{-3}$ & Embed.\ collapse \\
114	v5 & DeBERTa & LoRA, m\_lr $10^{-4}$ & NaN gradients \\
115	v6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\% ($-$13.7pp) \\
116	\bottomrule
117	\end{tabular}}
118	\end{table}
119	
120	\subsection{Zero-Shot LLM Prompt Template}
121	\label{app:zeroshot_prompt}
122	
123	Both DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.
124	The system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).
125	The user message presents the passage (truncated to ${\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.
126	No in-context examples are provided.
127	
128	\begin{quote}
129	\small
130	\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\ldots]''
131	
132	\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \{text\}. Respond with ONLY a JSON object: \{\texttt{"depth"}: $\langle$int 0--3$\rangle$, \texttt{"confidence"}: $\langle$float 0--1$\rangle$, \texttt{"reasoning"}: $\langle$str$\rangle$\}''
133	\end{quote}
134	
135	\subsection{Temperature Robustness}
136	\label{app:multi_tau}
137	
138	The cross-strategy results in \S\ref{sec:gen:crossstrategy} use a single temperature ($\tau{=}0.9$).
139	To test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\tau \in \{0.5, 0.7, 0.9, 1.1\}$ on Pythia-1.4B.
140	
141	\paragraph{Within-$\tau$ robustness.}
142	For $\tau \in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\% to 77.3\% (Table~\ref{tab:multi_tau_within}); the depth signal is therefore not an artifact of a single temperature.
143	The same top-5 features (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{mean\_surprisal}, \texttt{p75\_ppl}) dominate across all $\tau$ values with only minor rank-order variation.
144	
145	\paragraph{Collapse at $\tau{=}1.1$: memorization as prerequisite.}
146	At $\tau{=}1.1$, 4-class accuracy drops to 57.2\% and d1v2 AUC falls to 0.528.
147	Training loss reveals the mechanism: at low temperature ($\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \to 0.42 \to 0.16$), a sign of rapid memorization of the model's own output.
148	At $\tau{=}1.1$, loss remains nearly flat ($2.27 \to 1.91 \to 1.85$); high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.
149	This establishes \emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.
150	
151	\paragraph{Cross-$\tau$ non-transferability.}
152	Leave-one-$\tau$-out transfer yields mean accuracy of 46.7\% with mean d1v2 AUC of 0.319 (Table~\ref{tab:multi_tau_cross}), worse than cross-strategy transfer (59.1\%; \S\ref{sec:gen:crossstrategy}).
153	Holdout $\tau{=}0.5$ produces inverted d1v2 AUC (0.176); different temperatures therefore produce surprisal distributions with incompatible shapes.
154	This extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific; strategy-conditioned classifiers are therefore necessary.
155	
156	\paragraph{Ecological validity.}
157	On WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity, partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.
158	On noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.
159	
160	\begin{table}[h]
161	\centering
162	\small
163	\caption{Within-$\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\ depth $j$.}
164	\label{tab:multi_tau_within}
165	\resizebox{\columnwidth}{!}{%
166	\begin{tabular}{@{}lcccc@{}}
167	\toprule
168	$\tau$ & 4-class acc (\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\
169	\midrule
170	0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\
171	0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\
172	0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\
173	1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\
174	\bottomrule
175	\end{tabular}}
176	\end{table}
177	
178	\begin{table}[h]
179	\centering
180	\small
181	\caption{Cross-$\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}
182	\label{tab:multi_tau_cross}
183	\begin{tabular}{@{}lcc@{}}
184	\toprule
185	Holdout & Acc (\%) & d1v2 AUC \\
186	\midrule
187	$\tau{=}0.5$ & 52.2 & 0.176 \\
188	$\tau{=}0.7$ & 41.0 & 0.299 \\
189	$\tau{=}0.9$ & 46.4 & 0.277 \\
190	$\tau{=}1.1$ & 47.1 & 0.525 \\
191	\midrule
192	Mean & 46.7 & 0.319 \\
193	\bottomrule
194	\end{tabular}
195	\end{table}
196	
197	\subsection{Feature Overlap Analysis}
198	\label{app:feature_overlap}
199	
200	We probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.
201	PLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics; \texttt{var\_surprisal} and \texttt{p90\_ppl} yield negative $R^2$ under linear probing; these features are not linearly accessible in the pretrained representation space.
202	This confirms that the 20pp accuracy gap between feature-based and end-to-end methods (\S\ref{app:e2e}) stems from complementary, not redundant, representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.
203	
204	\subsection{End-to-End Learning}
205	\label{app:e2e}
206	
207	DeBERTa-v3-base \cite{he2021_deberta_v3} and RoBERTa-base \cite{liu2019_roberta} finetuned end-to-end achieve 58.3\% ($\pm$4.7\%) and 59.5\% ($\pm$3.2\%) respectively, lagging the RF baseline (78.7\%) by 20.4pp and 19.2pp.
208	The 1.2pp inter-backbone gap rules out architecture bias; Table~\ref{tab:e2e_detail} shows both backbones share the same failure mode (high d0 F1, $>$0.94, but collapsed d1/d2 performance, F1 $\leq$ 0.42), while RF achieves 0.596 d2 recall, a $>$2$\times$ advantage at the hardest depth class.
209	
210	\begin{table}[h]
211	\centering
212	\small
213	\caption{Per-class performance for end-to-end PLM classifiers vs.\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}
214	\label{tab:e2e_detail}
215	\resizebox{\columnwidth}{!}{%
216	\begin{tabular}{@{}lccccc@{}}
217	\toprule
218	Method & Acc (\%) & d0 & d1 & d2 & d3 \\
219	\midrule
220	DeBERTa-v3 & 58.3\,$\pm$\,4.7 & .947 & .378 & .247 & .656 \\
221	RoBERTa-base & 59.5\,$\pm$\,3.2 & .958 & .416 & .261 & .647 \\
222	\midrule
223	RF (19 feat.) & 78.7 & --- & --- & .596$^\dagger$ & --- \\
224	\bottomrule
225	\multicolumn{6}{@{}l}{\footnotesize $^\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}
226	\end{tabular}}
227	\end{table}
228	
229	\paragraph{Feature space divergence.}
230	SHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\% of RF's total contribution.
231	Three independent importance measures (SHAP, Gini, and permutation) show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \S\ref{app:permutation}), with \texttt{p90\_ppl} appearing in the SHAP top-2 in 9/9 cells and \texttt{var\_surprisal} in 8/9.
232	Linear probing of PLM [CLS] representations yields negative $R^2$ for both \texttt{var\_surprisal} and \texttt{p90\_ppl} (\S\ref{app:feature_overlap}); pretrained representations lack the linear structure needed to recover perplexity tail statistics, a systematic representational gap rather than a backbone-specific artifact.
233	
234	DCOL \cite{cloc2025} reached 64.5\% (\S\ref{app:dcol_iterations}); all end-to-end approaches (58--65\%) underperform feature-based methods; depth estimation therefore benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.
235	This comparison is bounded by backbone scale ($\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.
236	
237	\subsection{Domain Bias Analysis}
238	\label{app:domain_bias}
239	
240	To assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.
241	
242	\paragraph{Methodological note.}
243	An initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\%, seed-group prediction 20.8\%).
244	We discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.
245	The results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.
246	
247	\paragraph{Sub-A: Standard CV.}
248	Five-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\% to 82\% across the 9 atlas cells (up to 2.5$\times$ above the 33.3\% chance level); depth signal is therefore the dominant classification factor.
249	
250	\paragraph{Sub-B: LOGO evaluation.}
251	We assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.
252	LOGO mean accuracy is 72.1\% (range 59.5--81.6\%), matching standard CV (72.0\%) within noise (before fix: 64.0\%, reflecting the depth--group confound).
253	Per-cell fold standard deviations range from 0.4pp to 1.4pp; cross-group generalization is therefore as reliable as within-group classification.
254	
255	\paragraph{Sub-C: Negative control.}
256	We train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\%).
257	Depth prediction accuracy averages 72.0\%; seed-group prediction averages 10.2\%, indistinguishable from chance (before fix: 20.8\%, inflated by the depth--group confound).
258	The depth-to-seed-group accuracy ratio is 7.1$\times$; the feature representation therefore encodes depth but not seed-article identity.
259	
260	Taken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.
261	
262	\subsection{Wild-Data Calibration}
263	\label{app:calibration}
264	
265	Table~\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages, crawled 2019--2020; pre-LLM deployment).
266	
267	\begin{table}[h]
268	\centering
269	\small
270	\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\% Wilson CIs computed for C4 ($n{=}5{,}000$).}
271	\label{tab:calibration}
272	\resizebox{\columnwidth}{!}{%
273	\begin{tabular}{@{}llrccc@{}}
274	\toprule
275	Model & Source & $n$ & d0 (\%) & FPR (\%) & 95\% Wilson CI \\
276	\midrule
277	Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\
278	 & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\
279	\addlinespace
280	GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\
281	 & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\
282	\addlinespace
283	OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\
284	 & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\
285	\bottomrule
286	\end{tabular}}
287	\end{table}
288	
289	On WikiText-103, all three classifiers achieve $\geq$98.5\% d0 accuracy; editorial text is therefore reliably distinguished from recursive generations across model families.
290	On C4, FPR varies sharply: OLMo (4.7\%) vs.\ Pythia (20.2\%) and GPT-2~XL (22.4\%).
291	C4 misclassifications concentrate in template and SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0 passages), rather than in random noise.
292	The model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.
293	Among C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\%), d2 (3.7\%), d3 (9.6\%); for OLMo, d1 (2.9\%), d2 (0.5\%), d3 (1.3\%). The non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.
294	
295	\paragraph{Threshold calibration.}
296	A pooled RF classifier (trained on all three families' nucleus data) achieves ECE\,=\,0.052 on in-distribution data; Platt scaling and isotonic regression yield no improvement; probability estimates are already well calibrated.
297	The high FPR on web-crawl data is therefore a decision-threshold problem, not a probability calibration defect.
298	Applying a confidence threshold $P(\mathrm{d0}) \geq 0.15$ reduces C4 FPR from 33.4\% to 2.8\% and FineWeb FPR from 16.9\% to 0.7\%, at a cost of only $-$0.3\,pp balanced accuracy (78.0\%$\to$77.7\%).
299	The $P(\mathrm{d0})$ distribution is bimodal: 67\% of samples exceed 0.95 (high-confidence d0), while 33\% fall in the 0.15--0.30 uncertainty zone; the threshold separates these modes cleanly.
300	Wild-data FPR is thus an operational threshold choice rather than a fundamental limitation, though the optimal threshold is domain-dependent.
301	
302	\subsection{Downstream Curation PoC}
303	\label{app:curation_poc}
304	
305	To assess whether depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.
306	We fine-tune Pythia-410M with LoRA ($r{=}16$, $\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.
307	Conditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\approx$25\%, moderate $\approx$50\%, soft threshold).
308	Table~\ref{tab:curation_poc} reports per-condition perplexity; Table~\ref{tab:curation_comparisons} reports pairwise contrasts.
309	
310	\begin{table}[h]
311	\centering
312	\small
313	\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\,: $p<0.05$ (paired $t$-test vs.\ unfiltered).}
314	\label{tab:curation_poc}
315	\resizebox{\columnwidth}{!}{%
316	\begin{tabular}{@{}lcccccc@{}}
317	\toprule
318	Condition & Mean PPL & Std & $n$ & $\Delta$ vs Unfilt. & $p$ & $d_z$ \\
319	\midrule
320	unfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\
321	rf\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\
322	rf\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\
323	rf\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\
324	oracle\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\
325	oracle\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\
326	random\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\
327	random\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\
328	random\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\
329	\bottomrule
330	\end{tabular}}
331	\end{table}
332	
333	\begin{table}[h]
334	\centering
335	\small
336	\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\,: $p<0.05$; $^{**}$\,: $p<0.01$.}
337	\label{tab:curation_comparisons}
338	\resizebox{\columnwidth}{!}{%
339	\begin{tabular}{@{}lccc@{}}
340	\toprule
341	Comparison & $\Delta$ PPL & $t$ & $p$ \\
342	\midrule
343	rf\_strict vs random\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\
344	rf\_moderate vs random\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\
345	rf\_soft vs random\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\
346	rf\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\
347	\bottomrule
348	\end{tabular}}
349	\end{table}
350	
351	RF-based depth filtering (19-feature F1\,=\,0.997) substantially outperforms a simple perplexity-threshold baseline (F1\,=\,0.845) for identifying low-depth passages; the multi-feature representation provides discriminative value beyond raw perplexity.
352	However, the primary comparison (RF-filtered vs.\ unfiltered, $p > 0.4$) is non-significant; the significant RF-vs-random contrasts ($p < 0.02$) involve multiple pairwise comparisons that were not corrected for multiplicity.
353	
354	\subsection{Reference Model Ablation}
355	\label{app:ref_ablation}
356	
357	\begin{table}[h]
358	\centering
359	\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}
360	\label{tab:ref_ablation}
361	\resizebox{\columnwidth}{!}{%
362	\begin{tabular}{@{}lcc@{}}
363	\toprule
364	Reference Model & Architecture & Accuracy (\%) \\
365	\midrule
366	Pythia-1.4B (self) & GPT-NeoX & 78.6 $\pm$ 0.6 \\
367	OLMo-1B (cross) & OLMo & 74.5 $\pm$ 0.7 \\
368	GPT-2~XL (cross) & GPT-2 & 67.3 $\pm$ 0.7 \\
369	\bottomrule
370	\end{tabular}}
371	\end{table}
372	
373	\subsection{Cross-Scale Full Results}
374	\label{app:cross_scale_full}
375	
376	This section provides the full cross-scale analysis summarized in \S\ref{sec:gen:crossscale}.
377	We extend the benchmark to two 7--8B models (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct) and one 14B model (Qwen2.5-14B-Instruct), all under 4-bit NF4 QLoRA fine-tuning with nucleus sampling ($p{=}0.95$, 500 samples per depth).
378	The 7--8B models generate depths $d \in \{0, 1, \ldots, 5\}$; the 14B model generates $d \in \{0, 1, 2, 3\}$.
379	Feature extraction for 1--8B models uses Pythia-1.4B as reference; Qwen2.5-14B uses self-reference (the 14B model computes its own perplexity features), a choice that precludes direct comparison with the Pythia-referenced pipeline (see confounds below).
380	
381	\paragraph{Scale comparison.}
382	Table~\ref{tab:cross_scale} contrasts the 7--14B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).
383	
384	\begin{table}[h]
385	\centering
386	\small
387	\caption{Cross-scale comparison: 4-class RF accuracy (\%, depths 0--3, nucleus), $\mathrm{EDD}_{T{=}0.70}$, and d0-vs-d1 AUC. CI: 95\% bootstrap. Chance = 25\%. $^\dagger$Self-reference model (see text).}
388	\label{tab:cross_scale}
389	\resizebox{\columnwidth}{!}{%
390	\begin{tabular}{@{}lccc@{}}
391	\toprule
392	Model & 4-class acc & $\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\
393	\midrule
394	GPT-2~XL (1.5B) & 84.3 & 4 & 0.999 \\
395	OLMo-1B & 78.9 & 4 & 0.997 \\
396	Pythia-1.4B & 78.7 & 4 & 0.998 \\
397	\midrule
398	Llama-3.1-8B & 70.2\,[68.3, 72.4] & 4 & 0.949 \\
399	Qwen2.5-7B & 60.1\,[58.0, 62.1] & ${>}5$ & 0.969 \\
400	\midrule
401	Qwen2.5-14B$^\dagger$ & 54.1\,[53.4, 54.7] & 0 & 0.643 \\
402	\bottomrule
403	\end{tabular}}
404	\end{table}
405	
406	\paragraph{(1) Depth signal persists at 7--8B scale.}
407	Both 7--8B models substantially exceed the 25\% chance baseline: Llama-3.1-8B achieves 70.2\% (95\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\% ($[58.0, 62.1]$); recursive depth therefore remains estimable from perplexity-based features even when the generator is 5--7$\times$ larger than the reference model.
408	Depth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).
409	
410	\paragraph{(2) EDD at 7--8B scale.}
411	At threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\ref{tab:cross_scale_auc}), yielding $\mathrm{EDD}_{T{=}0.70} > 5$, exceeding the $\mathrm{EDD}{=}4$ observed at 1--1.5B.
412	Llama-3.1-8B matches the smaller models at $\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.
413	Both larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\ 0.852 at 1--1.5B).
414	
415	\begin{table}[h]
416	\centering
417	\small
418	\caption{Consecutive binary AUC (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a U-shaped pattern with all pairs above $T$; Qwen2.5-14B$^\dagger$ (depths 0--3 only) has d0v1 below $T$, yielding $\mathrm{EDD}{=}0$.}
419	\label{tab:cross_scale_auc}
420	\begin{tabular}{@{}lccccc@{}}
421	\toprule
422	Model & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\
423	\midrule
424	Llama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\
425	Qwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\
426	Qwen2.5-14B$^\dagger$ & 0.643 & 0.713 & 0.728 & \multicolumn{2}{c}{--} \\
427	\bottomrule
428	\end{tabular}
429	\end{table}
430	
431	\paragraph{(3) Divergent AUC trajectories and instruction-tuning effect.}
432	Among instruction-tuned models, Llama-3.1-8B exhibits monotonic AUC decay consistent with the 1--1.5B pattern, while Qwen2.5-7B shows a U-shaped recovery beyond d2v3 (Table~\ref{tab:cross_scale_auc}).
433	A base-model control (Llama-3.1-8B without instruction tuning) clarifies the causal direction: the base model achieves 59.9\% four-class accuracy (95\% CI [57.8, 62.15], $\mathrm{EDD}_{0.70}{=}2$) with non-monotonic AUC decay (Table~\ref{tab:llama3_base_auc}), while the instruction-tuned variant reaches 70.2\% with strictly monotonic decay.
434	The base-model control experiment suggests instruction-tuning regularizes rather than confounds the depth signal.
435	
436	\begin{table}[h]
437	\centering
438	\small
439	\caption{Pairwise AUC: Llama-3.1-8B Base vs.\ Instruct.}
440	\label{tab:llama3_base_auc}
441	\begin{tabular}{lccccc}
442	\toprule
443	Variant & $d_{0\text{v}1}$ & $d_{1\text{v}2}$ & $d_{2\text{v}3}$ & $d_{3\text{v}4}$ & $d_{4\text{v}5}$ \\
444	\midrule
445	Base & 0.918 & 0.794 & 0.682 & 0.730 & 0.595 \\
446	Instruct & 0.965 & 0.874 & 0.771 & 0.716 & 0.618 \\
447	\bottomrule
448	\end{tabular}
449	\end{table}
450	
451	The base model exhibits non-monotonic decay with a U-shaped recovery at $d_{3\text{v}4}$, while the instruction-tuned variant shows strictly monotonic decay. Both variants exceed chance (AUC $> 0.5$) at all boundaries; depth signal exists regardless of instruction-tuning, though instruction-tuning strengthens and regularizes it.
452	
453	\paragraph{(4) Signal attenuation at 14B.}
454	Qwen2.5-14B represents a boundary condition: four-class accuracy drops to 54.1\% (95\% CI $[53.4, 54.7]$, $2.2\times$ chance), with $\mathrm{EDD}_{0.70}{=}0$ because d0-vs-d1 AUC (0.643) falls below the 0.70 threshold (Table~\ref{tab:cross_scale_auc}).
455	The d0/d1 boundary, near-perfect at 1--1.5B (AUC ${>}0.99$), nearly vanishes at 14B.
456	Inter-depth discrimination at d1--d3 remains comparable: d1v2 AUC (0.713) and d2v3 AUC (0.728) both exceed 0.70, and d1--d3 balanced accuracy reaches 57.4\% (chance = 33\%).
457	Feature importance undergoes a structural shift: higher-order moments (kurtosis, skewness of perplexity) replace first/second-order statistics (\texttt{p90\_ppl}, variance) as top features, consistent with the theoretical prediction that increased model capacity compresses perplexity tails (\S\ref{sec:method:theory}); first-order tail statistics become less informative while higher-order shape changes persist.
458	This result carries an important caveat: Qwen2.5-14B uses self-reference (the 14B model computes its own perplexity features), whereas all other experiments use Pythia-1.4B.
459	Self-reference conflates the generator's distributional shift with the reference model's sensitivity; the observed attenuation may partially reflect the reference model change rather than a pure scale effect.
460	
461	\paragraph{Caveats.}
462	For Qwen2.5-7B, the CI lower bound (58.0\%) does not exclude sub-60\% accuracy; Llama-3.1-8B's lower bound (68.3\%) is more comfortably above chance but still below the 75--83\% range at 1--1.5B.
463	The divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.
464	
465	\paragraph{Confounds.}
466	\label{app:cross_scale_confounds}
467	Five confounds limit these results: (1)~4-bit NF4 QLoRA quantization (absent at 1--1.5B) may distort the perplexity distribution independently of depth; (2)~smaller sample size (500 vs.\ 5{,}000 per depth) widens confidence intervals; (3)~evaluation is limited to nucleus sampling, leaving other strategies untested at this scale; (4)~vocabulary mismatch between larger generators and the 1.4B reference model; (5)~Qwen2.5-14B uses self-reference rather than the Pythia-1.4B reference used for all other experiments, preventing direct cross-scale comparison at the 14B data point.
468	The base-model control partially addresses a former confound (instruction-tuning): since the base variant shows weaker signal with non-monotonic decay while the instruction-tuned variant shows stronger monotonic signal, instruction-tuning regularizes rather than confounds depth estimation.
469	The remaining confounds are not mutually independent (quantization and vocabulary mismatch both affect the perplexity distribution); it is therefore infeasible to attribute the observed accuracy gap (60--70\% vs.\ 78--85\% at 1--1.5B) to any single factor.
470	
471	\subsection{Cross-Boundary Generalization}
472	\label{app:cross_boundary}
473	
474	The preceding experiments assume a single model family generates all recursive depths.
475	In practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.
476	We probe whether the depth signal persists under two relaxations of the single-model assumption.
477	
478	\paragraph{Cross-model recursive chains.}
479	We construct a heterogeneous chain: human text (d0) $\to$ Pythia-1.4B generates d1 $\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.
480	Each recursive step uses a \emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.
481	A 4-class Random Forest achieves 84.75\% accuracy (95\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).
482	Pairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.
483	These results suggest that distributional artifacts of recursive generation persist across model boundaries. This constitutes preliminary evidence for a process-level depth signal rather than individual generator artifacts.
484	
485	\paragraph{Confound discussion.}
486	The heterogeneous chain confounds architecture identity with depth (d1=Pythia, d2=OLMo, d3=GPT-2~XL).
487	However, if the classifier exploited architecture fingerprints rather than depth signal, near-perfect accuracy would be expected since architecture perfectly determines depth label.
488	The observed 84.75\% with monotonically decreasing per-depth F1 (d0=0.98, d1=0.88, d2=0.76, d3=0.76) is more consistent with a depth-signal interpretation, as architecture fingerprinting would not produce this graded pattern.
489	We address this confound directly with a reverse-chain control below.
490	
491	\paragraph{Reverse-chain control.}
492	To empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\to$ OLMo $\to$ Pythia) reversing the model-depth assignment.
493	The reverse chain achieves 85.75\% (95\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\%, [81.0, 88.25]).
494	If the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.
495	
496	\paragraph{Cross-domain transfer.}
497	All prior experiments use WikiText-103 as the seed corpus.
498	To test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).
499	Five-fold cross-validation yields 74.1\% $\pm$ 2.0\% accuracy, compared to ${\sim}$78\% on the WikiText seed.
500	Per-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66, with d2 remaining the most challenging class.
501	The 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.
502	These results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.
503	
504	\subsection{Cross-Seed Replication}
505	\label{app:seed_replication}
506	
507	Table~\ref{tab:seed_replication} reports within-seed accuracy for all three model families (nucleus, depths 0--3) under two independent LoRA training seeds.
508	
509	\begin{table}[h]
510	\centering
511	\small
512	\caption{Cross-seed replication (nucleus $p{=}0.95$, d0--d3). seed=42 is the primary benchmark (matching Table~\ref{tab:main_matrix}); seed=43 is an independent replication.}
513	\label{tab:seed_replication}
514	\begin{tabular}{@{}llccc@{}}
515	\toprule
516	Model & Seed & Acc (\%) & 95\% CI & $\Delta$ (pp) \\
517	\midrule
518	Pythia-1.4B & 42 & 78.70 & [78.10, 79.24] & --- \\
519	Pythia-1.4B & 43 & 78.84 & [78.13, 79.52] & $+$0.14 \\
520	\midrule
521	OLMo-1B & 42 & 78.94 & [78.38, 79.48] & --- \\
522	OLMo-1B & 43 & 82.11 & [81.77, 82.54] & $+$3.17 \\
523	\midrule
524	GPT-2~XL & 42 & 84.28 & [83.78, 84.80] & --- \\
525	GPT-2~XL & 43 & 86.32 & [86.17, 86.49] & $+$2.04 \\
526	\bottomrule
527	\end{tabular}
528	\end{table}
529	
530	Seed=43 yields higher accuracy in all three models ($+$0.14 to $+$3.17\,pp, same direction).
531	For Pythia ($+$0.14\,pp), CIs overlap, consistent with noise; for OLMo ($+$3.17\,pp) and GPT-2~XL ($+$2.04\,pp), CIs do not overlap, so LoRA initialization has a non-trivial effect on absolute accuracy (${\sim}$1--3\,pp).
532	Top-3 features are identical across all seeds and models (\texttt{p90\_ppl}, \texttt{var\_surprisal}, \texttt{p75\_ppl}); depth ordering is preserved in every configuration.
533	
534	\paragraph{Outlier handling.}
535	Feature extraction occasionally produces extreme perplexity values (outlier passages); we apply per-feature clipping at $\pm 10^{10}$ before classification, affecting ${<}0.1$\% of samples.
536	The d3 perplexity distribution varies substantially across seeds: under seed=42, 0.56\% of d3 passages exceed $10^6$ in raw perplexity, while under seed=43 this fraction rises to 12.8\%.
537	Despite this variation, the classifier remains effective after clipping, confirming that the depth signal resides in the p90-and-below distributional shape rather than extreme outliers.
538	
539	\subsection{Depth-4 Extension}
540	\label{app:depth4_ext}
541	
542	We extend all three model families (GPT-2~XL, Pythia-1.4B, OLMo-1B; nucleus $p{=}0.95$) to depth~4 and train 5-class RF classifiers (d0--d4, 5{,}000 samples per depth).
543	Five-class accuracy reaches 80.5\% (OLMo), 74.0\% (GPT-2~XL), and 71.3\% (Pythia), all substantially above the 20\% chance baseline.
544	For Pythia and GPT-2~XL, d3 recall drops from ${\sim}$80\% (4-class) to ${\sim}$49\% (5-class) due to d3/d4 confusion; d4 recall is higher (Pythia 68.1\%, GPT-2~XL 63.9\%).
545	$\mathrm{EDD}_{0.70} \geq 4$ was established by dedicated binary classifiers in the atlas (\S\ref{sec:atlas:edd}; d3v4 AUC: Pythia 0.784, OLMo 0.765, GPT-2~XL 0.750); the 5-class results provide complementary evidence that depth~4 remains discriminable in the multi-class setting.
546	
547	\paragraph{Feature monotonicity at d4.}
548	For Pythia and GPT-2~XL, the dominant depth markers (\texttt{p90\_ppl}, \texttt{var\_surprisal}) maintain monotonic decrease through d4 (Pythia \texttt{p90\_ppl}: $483.7 \to 12.5$ from d0 to d4; \texttt{var\_surprisal}: $6.50 \to 1.29$), consistent with continued tail erosion (\S\ref{sec:method:theory}).
549	Mean perplexity breaks monotonicity at d4 for GPT-2~XL (d3: $1{,}076\mathrm{K}$ $\to$ d4: $928\mathrm{K}$) while tail perplexity continues to decline.
550	OLMo exhibits a \texttt{var\_surprisal} rebound at d4 ($2.49 \to 2.83$, non-monotonic), creating a feature signature absent in GPT-2~XL and Pythia.
551	The 5-class RF exploits non-adjacent depth contrasts (particularly d0-vs-d4 and d2-vs-d4) to achieve 80.5\% accuracy, the highest among all three families, while the dedicated binary d3-vs-d4 classifier (AUC 0.765) is restricted to adjacent-depth features.
552	This discrepancy illustrates that multi-class classifiers can leverage global distributional structure unavailable to pairwise comparisons.
553	The divergence between aggregate and tail statistics suggests that aggregate distributional statistics saturate at deep recursion while tail statistics continue to shift.
554	This saturation provides a physical mechanism for the EDD ceiling: once per-step feature change falls below classifier resolution, adjacent depths become indistinguishable regardless of continued distributional drift.
555	
556	\subsection{Generation Length Ablation}
557	\label{app:length_ablation}
558	
559	Table~\ref{tab:length_ablation} reports classification accuracy as a function of passage length (Pythia-1.4B nucleus, depths 0--3).
560	
561	\begin{table}[h]
562	\centering
563	\small
564	\caption{Generation length ablation (Pythia-1.4B nucleus, 5-fold CV). Accuracy increases monotonically with passage length; the 9.47\,pp spread confirms that longer passages provide stronger statistical signal.}
565	\label{tab:length_ablation}
566	\begin{tabular}{@{}lc@{}}
567	\toprule
568	Passage length (tokens) & Acc (\%) \\
569	\midrule
570	128 & 68.35 \\
571	256 & 73.80 \\
572	512 & 77.82 \\
573	\bottomrule
574	\end{tabular}
575	\end{table}
576	
577	Depth signal is detectable from 128 tokens (2.7$\times$ chance) and saturates near 500 tokens.
578	The monotonic increase reflects the statistical nature of the features: longer passages yield more stable estimates of perplexity percentiles and surprisal variance, reducing within-class overlap at adjacent depth boundaries.
579	
580	\subsection{Mixed-Depth Corpus}
581	\label{app:mixed_depth}
582	
583	Per-passage classification is largely independent of corpus composition: evaluating on a corpus containing mixed proportions of d0--d3 passages (rather than balanced classes) yields macro-recall $\Delta{=}{-}1.62$\,pp relative to the balanced benchmark (within the 2\,pp tolerance).
584	Individual class deltas range from $-$0.45\,pp to $-$2.43\,pp (d1 shows the largest shift); the RF classifier operates on per-sample features without sensitivity to the class distribution of the evaluation corpus.
585	Macro-recall $\Delta$ = $-$1.62\,pp (within the 2\,pp threshold); individual class variations (max 2.43\,pp on d1) arise from held-out sample composition rather than classifier sensitivity to corpus distribution, as the Random Forest produces identical per-sample predictions regardless of batch context.
586	
587	\subsection{Learned Estimator Comparison}
588	\label{app:learned_estimator}
589	
590	Table~\ref{tab:learned_estimator} evaluates three learned classifiers (XGBoost, ordinal MLP with CORAL loss \cite{coral2020}, prototypical networks) under the same leave-one-model-out protocol as Table~\ref{tab:cross_model}.
591	The ordinal MLP follows the nested binary reduction framework \cite{mccullagh1980_ordinal,frank2001} with the loss function of \citet{rennie2005}.
592	All three methods operate on the same 19-dimensional feature vector; the comparison isolates the effect of the classification head.
593	
594	\begin{table}[h]
595	\centering
596	\small
597	\caption{Learned estimator cross-model transfer (leave-one-model-out, nucleus, 4-class). RF baseline from Table~\ref{tab:cross_model}. Chance = 25\%.}
598	\label{tab:learned_estimator}
599	\begin{tabular}{@{}lcccc@{}}
600	\toprule
601	Method & Pythia & OLMo & GPT-2 XL & Mean \\
602	\midrule
603	RF (baseline) & --- & --- & --- & 66.4 \\
604	XGBoost & 63.7 & 69.8 & 68.1 & 67.2 \\
605	Ordinal MLP & 62.5 & 69.7 & 67.9 & 66.7 \\
606	Prototypical & 61.6 & 70.0 & 68.4 & 66.6 \\
607	\bottomrule
608	\end{tabular}
609	\end{table}
610	
611	All three learned methods match the RF baseline within 0.8\,pp on average; the Pythia holdout is consistently the hardest (61.6--63.7\%), while OLMo and GPT-2~XL holdouts yield 67.9--70.0\%.
612	The narrow spread ($\leq$0.8\,pp across four methods) reinforces the conclusion that the 19-feature representation, not the classifier, determines the accuracy ceiling in the cross-model transfer setting.
613	
614	\subsection{Instruction-Tuned Model at 1.5B Scale}
615	\label{app:instruct_1p5b}
616	
617	To test whether instruction tuning eliminates depth signal at matched scale (1.5B, avoiding the quantization confound of \S\ref{sec:gen:crossscale}), we run the full recursive pipeline on Qwen2.5-1.5B-Instruct with self-reference feature extraction (i.e., the same model serves as both generator and reference).
618	
619	The RF classifier achieves 47.4\% four-class accuracy (95\% CI $[46.7, 48.1]$, $1.9\times$ chance); instruction tuning therefore reduces but does not eliminate depth signal.
620	The pairwise AUC profile differs from base models: d0v1 = 0.653, d1v2 = 0.620, d2v3 = 0.664, with a gap-dependent pattern (non-adjacent pairs yield higher AUC, e.g., d0v3 = 0.902) but no pair reaching the 0.75 threshold.
621	
622	The top-5 features shift substantially: \texttt{surprisal\_range}, \texttt{surprisal\_position\_corr}, \texttt{prob\_std}, \texttt{surprisal\_first\_half\_minus\_second}, and \texttt{surprisal\_std} replace the perplexity tail statistics (\texttt{p90\_ppl}, \texttt{var\_surprisal}) that dominate in base models.
623	This feature shift suggests instruction tuning compresses the perplexity distribution (reducing tail discriminability) while preserving positional and range-based surprisal patterns.
624	
625	Two caveats apply: (1) self-reference evaluation may inflate or deflate accuracy relative to cross-reference evaluation (cf.\ \S\ref{app:ref_ablation}); (2) a single instruction-tuned model does not establish the generality of the feature shift across architectures or instruction-tuning recipes.
626	
627	\subsection{Downstream Fine-Tuning Probe}
628	\label{app:downstream}
629	
630	We fine-tune Pythia-410M with LoRA ($r{=}16$, $\alpha{=}32$) on depth-stratified subsets (500 samples each) and evaluate held-out perplexity (200 samples, 50 per depth).
631	
632	\begin{table}[h]
633	\centering
634	\small
635	\caption{Downstream fine-tuning probe: held-out perplexity by training subset (Pythia-410M LoRA, seed=42). $\Delta$: signed difference vs.\ baseline (negative = better).}
636	\label{tab:downstream}
637	\begin{tabular}{@{}lcc@{}}
638	\toprule
639	Training subset & PPL & $\Delta$ vs.\ baseline \\
640	\midrule
641	Baseline (no fine-tuning) & 5.67 & --- \\
642	d0 only & 5.65 & $-$0.02 \\
643	d1 only & 5.55 & $-$0.12 \\
644	d2 only & 5.56 & $-$0.11 \\
645	Mixed (d0--d3) & 5.55 & $-$0.12 \\
646	\bottomrule
647	\end{tabular}
648	\end{table}
649	
650	The hypothesis that d0-only data yields the lowest perplexity is not supported: d1-only and mixed subsets tie for best (PPL~5.55), both marginally below d0-only (5.65).
651	The PPL spread is small (0.12, 2.1\% relative) and the sample size (500 per condition, single seed) is insufficient for statistical significance.
652	Training loss decreases monotonically with depth (d0: 2.558, d1: 1.920, d2: 1.286), consistent with recursive generation reducing information content and making text easier to model.
653	This pilot establishes that depth-filtered data is not harmful for downstream fine-tuning; whether depth-aware curation provides a meaningful advantage requires larger-scale evaluation.
654	
655	\subsection{Feature Group Ablation}
656	\label{app:feature_ablation}
657	
658	Table~\ref{tab:feature_ablation} reports cross-model transfer accuracy (leave-one-model-out, nucleus) when restricting the classifier to subsets of the 19-feature vector, grouped by signal type.
659	
660	\begin{table}[h]
661	\centering
662	\small
663	\caption{Feature group ablation (cross-model LOO, nucleus, 4-class). Chance = 25\%.}
664	\label{tab:feature_ablation}
665	\begin{tabular}{@{}lccc@{}}
666	\toprule
667	Feature group & \#Feat. & Acc (\%) & $\Delta$ vs.\ Full \\
668	\midrule
669	Full (all 19) & 19 & 66.6 & --- \\
670	Perplexity only & 9 & 66.0 & $-$0.5 \\
671	Entropy/Surprisal only & 5 & 63.2 & $-$3.4 \\
672	Repetition/Diversity only & 5 & 53.0 & $-$13.6 \\
673	\midrule
674	\texttt{p90\_ppl} only & 1 & 58.3 & $-$8.3 \\
675	\bottomrule
676	\end{tabular}
677	\end{table}
678	
679	The 9 perplexity features nearly match the full set ($\Delta{=}{-}0.5$\,pp), while repetition/diversity features alone fall 13.6\,pp below; perplexity degradation statistics therefore carry the dominant depth signal.
680	The top-2 individual features by Gini importance are \texttt{p90\_ppl} (22.4\%) and \texttt{var\_surprisal} (18.8\%), accounting for 41\% of total importance.
681	
682	\subsection{RF Seed Robustness}
683	\label{app:rf_seed}
684	
685	Table~\ref{tab:rf_seed} reports cross-model transfer accuracy across three RF random seeds.
686	
687	\begin{table}[h]
688	\centering
689	\small
690	\caption{RF seed robustness (cross-model LOO, nucleus, 4-class).}
691	\label{tab:rf_seed}
692	\begin{tabular}{@{}lc@{}}
693	\toprule
694	Seed & Acc (\%) \\
695	\midrule
696	42 & 66.4 \\
697	123 & 66.5 \\
698	456 & 66.5 \\
699	\midrule
700	Mean $\pm$ std & 66.48 $\pm$ 0.06 \\
701	\bottomrule
702	\end{tabular}
703	\end{table}
704	
705	The 0.06\,pp standard deviation across seeds confirms that RF classification is deterministic to within rounding noise at this sample size, and reported accuracy differences across experimental conditions (e.g., feature ablation, cross-model transfer) are not attributable to classifier randomness.
706	
707	\subsection{Binary Detector Baselines for Ordinal Classification}
708	\label{app:detector_baselines}
709	
710	We evaluate whether existing binary AI-text detectors and membership inference methods, when repurposed for ordinal classification, can match our 19-feature RF pipeline.
711	
712	\paragraph{Binary detectors (Pythia nucleus).}
713	Binoculars~\cite{binoculars2024} and Fast-DetectGPT~\cite{fast_detectgpt2024} scores are computed on the Pythia-1.4B nucleus ($p{=}0.95$) subset and fed to: (a)~a log-likelihood rank classifier (Log-Rank, 64.0\%), (b)~a combined RF trained on both detector scores (Combined, 74.2\%), and (c)~the standard 19-feature RF (78.7\%).
714	The 4.5\,pp gap (74.2\% vs.\ 78.7\%) confirms that perplexity distributional features capture ordinal depth structure beyond what generic detection scores provide.
715	Note that Fast-DetectGPT exhibits numerical overflow on Pythia nucleus d1 (mean perturbation score $>$28{,}000); results for this cell should be interpreted cautiously.
716	Across all 9 atlas cells, Binoculars and Fast-DetectGPT ordinal accuracy averages ${\sim}$35\% and ${\sim}$32\%, respectively.
717	
718	\paragraph{Membership inference baselines (all 9 cells).}
719	DetectGPT~\cite{mitchell2023_detectgpt} (gpt2-large scoring model, t5-large perturbation model, 5 perturbations) achieves 30.7\% mean 4-class accuracy (d1--d3 BalAcc: 24.3\%).
720	Min-K\% Prob~\cite{shi2024_minkprob} ($K{=}20$) with CORAL ordinal calibration reaches 33.2\% (d1--d3 BalAcc: 40.4\%); the best single cell is gpt2xl\_temp09 at 50.6\%.
721	Min-K\%'s advantage over DetectGPT (+2.5\,pp) is consistent with token-level log-probabilities containing more depth-relevant information than perturbation-based curvature, but both remain within 10\,pp of chance.
722	CORAL calibration improves ordinal structure (d1--d3 BalAcc 40.4\% vs.\ 33.3\% random) without closing the gap to RF (71.6\%), confirming that the bottleneck is the input signal rather than the calibration strategy.
723	The consistent failure of all four binary/membership methods (30--35\% vs.\ RF 78.4\%) confirms that ordinal depth estimation requires depth-specific distributional features inaccessible to detection scores designed for binary classification.
724	
725	\paragraph{Augmented feature set.}
726	To test whether detection scores carry complementary ordinal signal, we add Min-K\% probability ($K{=}20$) and DetectGPT perturbation discrepancy as additional RF features.
727	The 20-feature model (19 + Min-K\%) achieves 78.90\% mean 4-class accuracy (+0.48\,pp) and 72.20\% d1--d3 balanced accuracy (+0.60\,pp).
728	Min-K\% ranks \#3 by feature importance (0.095), behind \texttt{p90\_ppl} (0.161) and \texttt{var\_surprisal} (0.126); DetectGPT ranks \#17 (0.026).
729	The marginal improvement is consistent across 8 of 9 atlas cells, indicating that Min-K\%'s token-level log-probability signal provides weak but real complementary information to the passage-level distributional features.
730	The top-2 features (\texttt{p90\_ppl} + \texttt{var\_surprisal}) retain combined importance of 28.7\%, confirming that perplexity tail statistics remain the dominant depth markers even after augmentation.
731	
732	\subsection{Prompted Generation Results}
733	\label{app:prompted_gen}
734	
735	Table~\ref{tab:prompted_gen} reports depth estimation performance under topic-seeded (prompted) generation using GPT-2~XL with nucleus sampling ($p{=}0.95$, depths 0--3).
736	Generation is conditioned on Wikipedia topic prompts rather than a bare BOS token, a more ecologically valid test of depth signal persistence.
737	
738	\begin{table}[h]
739	\centering
740	\small
741	\caption{Prompted generation (GPT-2~XL, nucleus $p{=}0.95$, topic-seeded). 5-fold CV accuracy and pairwise AUC. Chance = 25\%.}
742	\label{tab:prompted_gen}
743	\begin{tabular}{@{}lc@{}}
744	\toprule
745	Metric & Value \\
746	\midrule
747	4-class accuracy (\%) & 69.52 $[68.9, 70.2]$ \\
748	BOS-seeded baseline (\%) & 83.3 \\
749	$\Delta$ (prompted $-$ BOS) & $-$13.78\,pp \\
750	\midrule
751	AUC d0v1 & 0.916 \\
752	AUC d1v2 & 0.782 \\
753	AUC d2v3 & 0.744 \\
754	\midrule
755	Top-1 feature & \texttt{p90\_ppl} \\
756	Top-2 feature & \texttt{var\_surprisal} \\
757	Top-3 feature & \texttt{p75\_ppl} \\
758	\bottomrule
759	\end{tabular}
760	\end{table}
761	
762	The 13.8\,pp drop relative to BOS-seeded generation is expected: topic prompts constrain the output distribution, reducing the variance that distinguishes depths.
763	Nevertheless, accuracy remains $2.8\times$ chance and pairwise AUC decays monotonically (0.916, 0.782, 0.744); the depth signal is therefore not an artifact of unconstrained generation.
764	Top features are identical to BOS-seeded (\texttt{p90\_ppl} first); the same perplexity tail erosion mechanism operates under prompted conditions.
765	
766	\subsection{Extended Discussion}
767	\label{app:extended_discussion}
768	
769	\paragraph{Cross-strategy conditional decomposition.}
770	The two-stage pipeline (strategy identification followed by depth classification) recovers 11.5\,pp over the na\"ive pooled classifier.
771	Under correct strategy routing, four-class accuracy reaches 72.6\% vs.\ 68.0\% under misrouting ($N{=}103{,}498$ / $76{,}502$), a gap of 4.6\,pp; d0 accuracy remains near-ceiling (${\sim}99.6$\%) regardless of routing, confirming that the d0 signal is strategy-invariant.
772	Even the worst routing yields a floor of 67.6\% ($2.7\times$ chance), and the 31.5\,pp d1--d3 gap between correct and wrong routing confirms feature-space misalignment rather than uniform noise.
773	End-to-end PLMs lag RF by ${\sim}20$\,pp, suggesting that current pretrained representations do not capture the distributional tail statistics that drive depth discrimination.
774	
775	\paragraph{Depth-graduated curation.}
776	Current data curation operates on a binary human-vs-machine distinction \cite{dsir2023,qurating2024}.
777	Recursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.
778	The 70--85\% in-distribution accuracy and $\mathrm{EDD}_{0.70}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\S\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a pilot study (Appendix~\ref{app:curation_poc}) yields an inconclusive RF-vs-unfiltered comparison ($p>0.4$), though RF-filtered subsets significantly outperform size-matched random subsampling ($p<0.001$--$0.02$); large-scale validation remains open.
779	Importance weighting \cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.
780	
781	\paragraph{Toward a provenance toolkit.}
782	Depth estimation complements existing provenance methods along orthogonal axes.
783	Watermarking \cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.
784	Source attribution \cite{uchendu2020_attribution} identifies the generating model but not the generation history.
785	Depth estimation characterizes \emph{iterative reuse} regardless of generator cooperation or identity.
786	A layered provenance system combining these three signals (watermark presence, source model, and recursive generation depth) could support more nuanced data auditing than any single method.
787	
788	\subsection{Computational Resources and Reproducibility}
789	\label{app:compute}
790	
791	\paragraph{Hardware.}
792	All experiments were conducted on 2$\times$ NVIDIA RTX PRO 6000 (48\,GB) GPUs locally and 2$\times$ NVIDIA RTX PRO 6000 (48\,GB) on cloud instances.
793	Total computation is approximately 200 GPU$\cdot$hours, covering the $3 \times 3$ generation matrix (LoRA fine-tuning + sampling at each depth), feature extraction, depth extension to d5, 7--14B QLoRA experiments, and all ablations.
794	
795	\paragraph{Software.}
796	Key library versions: PyTorch 2.10.0+cu128, Transformers 5.8.1, PEFT 0.7.1, scikit-learn 1.8.0.
797	Additional dependencies: Accelerate 1.13.0, Datasets 4.8.4, XGBoost 3.2.0, NumPy 2.2.6 (Python 3.12.3, CUDA 12.8).
798	
799	\paragraph{Hyperparameters.}
800	LoRA hyperparameters ($r{=}16$, $\alpha{=}32$, dropout $0.05$, lr $2{\times}10^{-4}$, batch size 8, 3 epochs) follow \citet{hu2022lora}.
801	The Random Forest classifier uses 200 trees, Gini criterion, and no max depth, without hyperparameter search; all reported results use 5-fold stratified cross-validation.
802	
803	\paragraph{Inference cost.}
804	Feature extraction and classification require no GPU.
805	Inference takes approximately 2 minutes per 5{,}000 samples on a single CPU core (reference-model forward pass + RF prediction), enabling deployment without specialized hardware.
806	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b37c39a3-a88d-435f-8238-19ed2ce96ebd",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "88ba207b-bd87-47a4-9fad-82e8a2b65134",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
      "content": "\\section{LoRA Fine-Tuning Protocol}\n\\label{app:lora_protocol}\n\nTable~\\ref{tab:lora_protocol} lists the full LoRA fine-tuning configuration used for recursive chain construction (\\S\\ref{sec:method:benchmark}).\nAt each depth $k$, a fresh LoRA adapter is initialized on the base model and trained on $\\mathcal{D}_{k-1}$; adapters are not inherited across depths.\nThe HuggingFace Trainer default linear decay schedule is used with no warmup.\nTarget modules are model-specific: \\texttt{query\\_key\\_value} (Pythia), \\texttt{att\\_proj} (OLMo), and \\texttt{c\\_attn} (GPT-2~XL).\nCross-scale experiments (\\S\\ref{sec:gen:crossscale}) use QLoRA (4-bit NF4) with $r{=}16$, $\\alpha{=}32$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{LoRA fine-tuning hyperparameters for the primary 1--1.5B benchmark. Identical across all three model families and all depth levels.}\n\\label{tab:lora_protocol}\n\\begin{tabular}{@{}ll@{}}\n\\toprule\nParameter & Value \\\\\n\\midrule\nLoRA rank $r$ & 16 \\\\\nLoRA alpha $\\alpha$ & 32 \\\\\nLoRA dropout & 0.05 \\\\\nBias & none \\\\\nEpochs per depth & 3 \\\\\nLearning rate & $2 \\times 10^{-4}$ \\\\\nLR schedule & linear decay (no warmup) \\\\\nBatch size (effective) & 16 ($8 \\times 2$ grad.\\ accum.) \\\\\nMax sequence length & 512 tokens \\\\\nPrecision & bfloat16 \\\\\nAdapter init & from scratch (base model) \\\\\nSeed & 42 (primary), 43 (replication) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Additional Results}\n\\label{app:additional}\n\n\\subsection{Top-$k$ Feature Trajectories}\n\\label{app:topk_trajectories}\n\nFigure~\\ref{fig:feature_trajectory} shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\\tau{=}0.9$) sampling.\nTop-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \\S\\ref{sec:atlas:strategy}.\nConcretely, the d0$\\to$d1 drop in \\texttt{p90\\_ppl} under top-$k$ is 78\\% (vs.\\ 87\\% for nucleus), and the d2$\\to$d3 reduction is 31\\% (vs.\\ 39\\% for nucleus).\nDespite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.\n\n\\subsection{Permutation Importance}\n\\label{app:permutation}\n\nTo verify that the Gini-based importance rankings in \\S\\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.\nThe top-2 features are stable across measures: \\texttt{p90\\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \\texttt{var\\_surprisal} in 8/9 (vs.\\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \\texttt{p75\\_ppl} displaces \\texttt{var\\_surprisal} to rank 3).\nKendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).\nPairwise Spearman correlations are: SHAP--Gini $\\rho{=}0.93$, SHAP--permutation $\\rho{=}0.84$, Gini--permutation $\\rho{=}0.76$.\nPer-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical; the top features are therefore robust to the choice of importance measure at the aggregate level, though per-cell rankings exhibit model-dependent variation.\n\n\\subsection{Feature Trajectories}\n\\label{app:feature_trajectories}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_feature_trajectory.pdf}\n\\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \\texttt{p90\\_ppl} (monotonically decreasing). Middle: \\texttt{var\\_surprisal} (decreasing). Bottom: \\texttt{rep\\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \\to d{=}1$ gap exceeds all subsequent inter-depth gaps.}\n\\label{fig:feature_trajectory}\n\\end{figure}\n\n\\subsection{Per-Class Recall}\n\\label{app:per_class}\n\nTable~\\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).\nDepth~0 recall exceeds 97\\% uniformly.\nAmong generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class recall (\\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}\n\\label{tab:per_class_recall}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & d0 & d1 & d2 & d3 \\\\\n\\midrule\nPythia, nuc.       & 99.3 & 81.9 & 59.2 & 74.4 \\\\\nPythia, $\\tau$     & 99.2 & 79.9 & 56.0 & 72.1 \\\\\nPythia, top-$k$    & 98.7 & 71.6 & 44.2 & 60.9 \\\\\nOLMo, nuc.         & 97.8 & 82.1 & 60.6 & 75.3 \\\\\nOLMo, $\\tau$       & 99.3 & 87.1 & 65.6 & 77.1 \\\\\nOLMo, top-$k$      & 99.2 & 80.9 & 50.4 & 67.2 \\\\\nGPT-2~XL, nuc.     & 98.5 & 87.4 & 72.8 & 78.5 \\\\\nGPT-2~XL, $\\tau$   & 99.0 & 91.1 & \\textbf{73.0} & 80.5 \\\\\nGPT-2~XL, top-$k$  & 98.7 & 81.3 & 54.8 & 68.4 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{DCOL Iteration Details}\n\\label{app:dcol_iterations}\n\nTable~\\ref{tab:dcol_iterations} summarizes all six DCOL iterations.\nDeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.7\\%.}\n\\label{tab:dcol_iterations}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}\n\\toprule\nVer. & Backbone & Config & Outcome \\\\\n\\midrule\nv1 & DeBERTa & FT, m\\_lr $10^{-3}$ & Embed.\\ collapse (31.5\\%) \\\\\nv2 & DeBERTa & FT, m\\_lr $10^{-4}$ & OOM \\\\\nv3 & DeBERTa & FT, m\\_lr $10^{-4}$ & Forgetting + OOM \\\\\nv4 & DeBERTa & LoRA, m\\_lr $10^{-3}$ & Embed.\\ collapse \\\\\nv5 & DeBERTa & LoRA, m\\_lr $10^{-4}$ & NaN gradients \\\\\nv6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\\% ($-$13.7pp) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\subsection{Zero-Shot LLM Prompt Template}\n\\label{app:zeroshot_prompt}\n\nBoth DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.\nThe system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).\nThe user message presents the passage (truncated to ${\\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.\nNo in-context examples are provided.\n\n\\begin{quote}\n\\small\n\\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\\ldots]''\n\n\\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \\{text\\}. Respond with ONLY a JSON object: \\{\\texttt{\"depth\"}: $\\langle$int 0--3$\\rangle$, \\texttt{\"confidence\"}: $\\langle$float 0--1$\\rangle$, \\texttt{\"reasoning\"}: $\\langle$str$\\rangle$\\}''\n\\end{quote}\n\n\\subsection{Temperature Robustness}\n\\label{app:multi_tau}\n\nThe cross-strategy results in \\S\\ref{sec:gen:crossstrategy} use a single temperature ($\\tau{=}0.9$).\nTo test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\\tau \\in \\{0.5, 0.7, 0.9, 1.1\\}$ on Pythia-1.4B.\n\n\\paragraph{Within-$\\tau$ robustness.}\nFor $\\tau \\in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\\% to 77.3\\% (Table~\\ref{tab:multi_tau_within}); the depth signal is therefore not an artifact of a single temperature.\nThe same top-5 features (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{mean\\_surprisal}, \\texttt{p75\\_ppl}) dominate across all $\\tau$ values with only minor rank-order variation.\n\n\\paragraph{Collapse at $\\tau{=}1.1$: memorization as prerequisite.}\nAt $\\tau{=}1.1$, 4-class accuracy drops to 57.2\\% and d1v2 AUC falls to 0.528.\nTraining loss reveals the mechanism: at low temperature ($\\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \\to 0.42 \\to 0.16$), a sign of rapid memorization of the model's own output.\nAt $\\tau{=}1.1$, loss remains nearly flat ($2.27 \\to 1.91 \\to 1.85$); high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.\nThis establishes \\emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.\n\n\\paragraph{Cross-$\\tau$ non-transferability.}\nLeave-one-$\\tau$-out transfer yields mean accuracy of 46.7\\% with mean d1v2 AUC of 0.319 (Table~\\ref{tab:multi_tau_cross}), worse than cross-strategy transfer (59.1\\%; \\S\\ref{sec:gen:crossstrategy}).\nHoldout $\\tau{=}0.5$ produces inverted d1v2 AUC (0.176); different temperatures therefore produce surprisal distributions with incompatible shapes.\nThis extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific; strategy-conditioned classifiers are therefore necessary.\n\n\\paragraph{Ecological validity.}\nOn WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity, partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.\nOn noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Within-$\\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\\ depth $j$.}\n\\label{tab:multi_tau_within}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$\\tau$ & 4-class acc (\\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\\\\n\\midrule\n0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\\\\n0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\\\\n0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\\\\n1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-$\\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}\n\\label{tab:multi_tau_cross}\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nHoldout & Acc (\\%) & d1v2 AUC \\\\\n\\midrule\n$\\tau{=}0.5$ & 52.2 & 0.176 \\\\\n$\\tau{=}0.7$ & 41.0 & 0.299 \\\\\n$\\tau{=}0.9$ & 46.4 & 0.277 \\\\\n$\\tau{=}1.1$ & 47.1 & 0.525 \\\\\n\\midrule\nMean & 46.7 & 0.319 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Feature Overlap Analysis}\n\\label{app:feature_overlap}\n\nWe probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.\nPLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics; \\texttt{var\\_surprisal} and \\texttt{p90\\_ppl} yield negative $R^2$ under linear probing; these features are not linearly accessible in the pretrained representation space.\nThis confirms that the 20pp accuracy gap between feature-based and end-to-end methods (\\S\\ref{app:e2e}) stems from complementary, not redundant, representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.\n\n\\subsection{End-to-End Learning}\n\\label{app:e2e}\n\nDeBERTa-v3-base \\cite{he2021_deberta_v3} and RoBERTa-base \\cite{liu2019_roberta} finetuned end-to-end achieve 58.3\\% ($\\pm$4.7\\%) and 59.5\\% ($\\pm$3.2\\%) respectively, lagging the RF baseline (78.7\\%) by 20.4pp and 19.2pp.\nThe 1.2pp inter-backbone gap rules out architecture bias; Table~\\ref{tab:e2e_detail} shows both backbones share the same failure mode (high d0 F1, $>$0.94, but collapsed d1/d2 performance, F1 $\\leq$ 0.42), while RF achieves 0.596 d2 recall, a $>$2$\\times$ advantage at the hardest depth class.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class performance for end-to-end PLM classifiers vs.\\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}\n\\label{tab:e2e_detail}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nMethod & Acc (\\%) & d0 & d1 & d2 & d3 \\\\\n\\midrule\nDeBERTa-v3 & 58.3\\,$\\pm$\\,4.7 & .947 & .378 & .247 & .656 \\\\\nRoBERTa-base & 59.5\\,$\\pm$\\,3.2 & .958 & .416 & .261 & .647 \\\\\n\\midrule\nRF (19 feat.) & 78.7 & --- & --- & .596$^\\dagger$ & --- \\\\\n\\bottomrule\n\\multicolumn{6}{@{}l}{\\footnotesize $^\\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Feature space divergence.}\nSHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\\% of RF's total contribution.\nThree independent importance measures (SHAP, Gini, and permutation) show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \\S\\ref{app:permutation}), with \\texttt{p90\\_ppl} appearing in the SHAP top-2 in 9/9 cells and \\texttt{var\\_surprisal} in 8/9.\nLinear probing of PLM [CLS] representations yields negative $R^2$ for both \\texttt{var\\_surprisal} and \\texttt{p90\\_ppl} (\\S\\ref{app:feature_overlap}); pretrained representations lack the linear structure needed to recover perplexity tail statistics, a systematic representational gap rather than a backbone-specific artifact.\n\nDCOL \\cite{cloc2025} reached 64.5\\% (\\S\\ref{app:dcol_iterations}); all end-to-end approaches (58--65\\%) underperform feature-based methods; depth estimation therefore benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.\nThis comparison is bounded by backbone scale ($\\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.\n\n\\subsection{Domain Bias Analysis}\n\\label{app:domain_bias}\n\nTo assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.\n\n\\paragraph{Methodological note.}\nAn initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\\%, seed-group prediction 20.8\\%).\nWe discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.\nThe results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.\n\n\\paragraph{Sub-A: Standard CV.}\nFive-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\\% to 82\\% across the 9 atlas cells (up to 2.5$\\times$ above the 33.3\\% chance level); depth signal is therefore the dominant classification factor.\n\n\\paragraph{Sub-B: LOGO evaluation.}\nWe assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.\nLOGO mean accuracy is 72.1\\% (range 59.5--81.6\\%), matching standard CV (72.0\\%) within noise (before fix: 64.0\\%, reflecting the depth--group confound).\nPer-cell fold standard deviations range from 0.4pp to 1.4pp; cross-group generalization is therefore as reliable as within-group classification.\n\n\\paragraph{Sub-C: Negative control.}\nWe train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\\%).\nDepth prediction accuracy averages 72.0\\%; seed-group prediction averages 10.2\\%, indistinguishable from chance (before fix: 20.8\\%, inflated by the depth--group confound).\nThe depth-to-seed-group accuracy ratio is 7.1$\\times$; the feature representation therefore encodes depth but not seed-article identity.\n\nTaken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.\n\n\\subsection{Wild-Data Calibration}\n\\label{app:calibration}\n\nTable~\\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages, crawled 2019--2020; pre-LLM deployment).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\\% Wilson CIs computed for C4 ($n{=}5{,}000$).}\n\\label{tab:calibration}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrccc@{}}\n\\toprule\nModel & Source & $n$ & d0 (\\%) & FPR (\\%) & 95\\% Wilson CI \\\\\n\\midrule\nPythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\\\\n & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\\\\n\\addlinespace\nGPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\\\\n & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\\\\n\\addlinespace\nOLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\\\\n & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nOn WikiText-103, all three classifiers achieve $\\geq$98.5\\% d0 accuracy; editorial text is therefore reliably distinguished from recursive generations across model families.\nOn C4, FPR varies sharply: OLMo (4.7\\%) vs.\\ Pythia (20.2\\%) and GPT-2~XL (22.4\\%).\nC4 misclassifications concentrate in template and SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0 passages), rather than in random noise.\nThe model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.\nAmong C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\\%), d2 (3.7\\%), d3 (9.6\\%); for OLMo, d1 (2.9\\%), d2 (0.5\\%), d3 (1.3\\%). The non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.\n\n\\paragraph{Threshold calibration.}\nA pooled RF classifier (trained on all three families' nucleus data) achieves ECE\\,=\\,0.052 on in-distribution data; Platt scaling and isotonic regression yield no improvement; probability estimates are already well calibrated.\nThe high FPR on web-crawl data is therefore a decision-threshold problem, not a probability calibration defect.\nApplying a confidence threshold $P(\\mathrm{d0}) \\geq 0.15$ reduces C4 FPR from 33.4\\% to 2.8\\% and FineWeb FPR from 16.9\\% to 0.7\\%, at a cost of only $-$0.3\\,pp balanced accuracy (78.0\\%$\\to$77.7\\%).\nThe $P(\\mathrm{d0})$ distribution is bimodal: 67\\% of samples exceed 0.95 (high-confidence d0), while 33\\% fall in the 0.15--0.30 uncertainty zone; the threshold separates these modes cleanly.\nWild-data FPR is thus an operational threshold choice rather than a fundamental limitation, though the optimal threshold is domain-dependent.\n\n\\subsection{Downstream Curation PoC}\n\\label{app:curation_poc}\n\nTo assess whether depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.\nWe fine-tune Pythia-410M with LoRA ($r{=}16$, $\\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.\nConditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\\approx$25\\%, moderate $\\approx$50\\%, soft threshold).\nTable~\\ref{tab:curation_poc} reports per-condition perplexity; Table~\\ref{tab:curation_comparisons} reports pairwise contrasts.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\\,: $p<0.05$ (paired $t$-test vs.\\ unfiltered).}\n\\label{tab:curation_poc}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\nCondition & Mean PPL & Std & $n$ & $\\Delta$ vs Unfilt. & $p$ & $d_z$ \\\\\n\\midrule\nunfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\\\\nrf\\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\\\\nrf\\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\\\\nrf\\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\\\\noracle\\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\\\\noracle\\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\\\\nrandom\\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\\\\nrandom\\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\\\\nrandom\\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\\,: $p<0.05$; $^{**}$\\,: $p<0.01$.}\n\\label{tab:curation_comparisons}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nComparison & $\\Delta$ PPL & $t$ & $p$ \\\\\n\\midrule\nrf\\_strict vs random\\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\\\\nrf\\_moderate vs random\\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\\\\nrf\\_soft vs random\\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\\\\nrf\\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nRF-based depth filtering (19-feature F1\\,=\\,0.997) substantially outperforms a simple perplexity-threshold baseline (F1\\,=\\,0.845) for identifying low-depth passages; the multi-feature representation provides discriminative value beyond raw perplexity.\nHowever, the primary comparison (RF-filtered vs.\\ unfiltered, $p > 0.4$) is non-significant; the significant RF-vs-random contrasts ($p < 0.02$) involve multiple pairwise comparisons that were not corrected for multiplicity.\n\n\\subsection{Reference Model Ablation}\n\\label{app:ref_ablation}\n\n\\begin{table}[h]\n\\centering\n\\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}\n\\label{tab:ref_ablation}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nReference Model & Architecture & Accuracy (\\%) \\\\\n\\midrule\nPythia-1.4B (self) & GPT-NeoX & 78.6 $\\pm$ 0.6 \\\\\nOLMo-1B (cross) & OLMo & 74.5 $\\pm$ 0.7 \\\\\nGPT-2~XL (cross) & GPT-2 & 67.3 $\\pm$ 0.7 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\subsection{Cross-Scale Full Results}\n\\label{app:cross_scale_full}\n\nThis section provides the full cross-scale analysis summarized in \\S\\ref{sec:gen:crossscale}.\nWe extend the benchmark to two 7--8B models (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct) and one 14B model (Qwen2.5-14B-Instruct), all under 4-bit NF4 QLoRA fine-tuning with nucleus sampling ($p{=}0.95$, 500 samples per depth).\nThe 7--8B models generate depths $d \\in \\{0, 1, \\ldots, 5\\}$; the 14B model generates $d \\in \\{0, 1, 2, 3\\}$.\nFeature extraction for 1--8B models uses Pythia-1.4B as reference; Qwen2.5-14B uses self-reference (the 14B model computes its own perplexity features), a choice that precludes direct comparison with the Pythia-referenced pipeline (see confounds below).\n\n\\paragraph{Scale comparison.}\nTable~\\ref{tab:cross_scale} contrasts the 7--14B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-scale comparison: 4-class RF accuracy (\\%, depths 0--3, nucleus), $\\mathrm{EDD}_{T{=}0.70}$, and d0-vs-d1 AUC. CI: 95\\% bootstrap. Chance = 25\\%. $^\\dagger$Self-reference model (see text).}\n\\label{tab:cross_scale}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nModel & 4-class acc & $\\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\\\\n\\midrule\nGPT-2~XL (1.5B) & 84.3 & 4 & 0.999 \\\\\nOLMo-1B & 78.9 & 4 & 0.997 \\\\\nPythia-1.4B & 78.7 & 4 & 0.998 \\\\\n\\midrule\nLlama-3.1-8B & 70.2\\,[68.3, 72.4] & 4 & 0.949 \\\\\nQwen2.5-7B & 60.1\\,[58.0, 62.1] & ${>}5$ & 0.969 \\\\\n\\midrule\nQwen2.5-14B$^\\dagger$ & 54.1\\,[53.4, 54.7] & 0 & 0.643 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{(1) Depth signal persists at 7--8B scale.}\nBoth 7--8B models substantially exceed the 25\\% chance baseline: Llama-3.1-8B achieves 70.2\\% (95\\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\\% ($[58.0, 62.1]$); recursive depth therefore remains estimable from perplexity-based features even when the generator is 5--7$\\times$ larger than the reference model.\nDepth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).\n\n\\paragraph{(2) EDD at 7--8B scale.}\nAt threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\\ref{tab:cross_scale_auc}), yielding $\\mathrm{EDD}_{T{=}0.70} > 5$, exceeding the $\\mathrm{EDD}{=}4$ observed at 1--1.5B.\nLlama-3.1-8B matches the smaller models at $\\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.\nBoth larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\\ 0.852 at 1--1.5B).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Consecutive binary AUC (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a U-shaped pattern with all pairs above $T$; Qwen2.5-14B$^\\dagger$ (depths 0--3 only) has d0v1 below $T$, yielding $\\mathrm{EDD}{=}0$.}\n\\label{tab:cross_scale_auc}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nModel & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\\\\n\\midrule\nLlama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\\\\nQwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\\\\nQwen2.5-14B$^\\dagger$ & 0.643 & 0.713 & 0.728 & \\multicolumn{2}{c}{--} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{(3) Divergent AUC trajectories and instruction-tuning effect.}\nAmong instruction-tuned models, Llama-3.1-8B exhibits monotonic AUC decay consistent with the 1--1.5B pattern, while Qwen2.5-7B shows a U-shaped recovery beyond d2v3 (Table~\\ref{tab:cross_scale_auc}).\nA base-model control (Llama-3.1-8B without instruction tuning) clarifies the causal direction: the base model achieves 59.9\\% four-class accuracy (95\\% CI [57.8, 62.15], $\\mathrm{EDD}_{0.70}{=}2$) with non-monotonic AUC decay (Table~\\ref{tab:llama3_base_auc}), while the instruction-tuned variant reaches 70.2\\% with strictly monotonic decay.\nThe base-model control experiment suggests instruction-tuning regularizes rather than confounds the depth signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise AUC: Llama-3.1-8B Base vs.\\ Instruct.}\n\\label{tab:llama3_base_auc}\n\\begin{tabular}{lccccc}\n\\toprule\nVariant & $d_{0\\text{v}1}$ & $d_{1\\text{v}2}$ & $d_{2\\text{v}3}$ & $d_{3\\text{v}4}$ & $d_{4\\text{v}5}$ \\\\\n\\midrule\nBase & 0.918 & 0.794 & 0.682 & 0.730 & 0.595 \\\\\nInstruct & 0.965 & 0.874 & 0.771 & 0.716 & 0.618 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe base model exhibits non-monotonic decay with a U-shaped recovery at $d_{3\\text{v}4}$, while the instruction-tuned variant shows strictly monotonic decay. Both variants exceed chance (AUC $> 0.5$) at all boundaries; depth signal exists regardless of instruction-tuning, though instruction-tuning strengthens and regularizes it.\n\n\\paragraph{(4) Signal attenuation at 14B.}\nQwen2.5-14B represents a boundary condition: four-class accuracy drops to 54.1\\% (95\\% CI $[53.4, 54.7]$, $2.2\\times$ chance), with $\\mathrm{EDD}_{0.70}{=}0$ because d0-vs-d1 AUC (0.643) falls below the 0.70 threshold (Table~\\ref{tab:cross_scale_auc}).\nThe d0/d1 boundary, near-perfect at 1--1.5B (AUC ${>}0.99$), nearly vanishes at 14B.\nInter-depth discrimination at d1--d3 remains comparable: d1v2 AUC (0.713) and d2v3 AUC (0.728) both exceed 0.70, and d1--d3 balanced accuracy reaches 57.4\\% (chance = 33\\%).\nFeature importance undergoes a structural shift: higher-order moments (kurtosis, skewness of perplexity) replace first/second-order statistics (\\texttt{p90\\_ppl}, variance) as top features, consistent with the theoretical prediction that increased model capacity compresses perplexity tails (\\S\\ref{sec:method:theory}); first-order tail statistics become less informative while higher-order shape changes persist.\nThis result carries an important caveat: Qwen2.5-14B uses self-reference (the 14B model computes its own perplexity features), whereas all other experiments use Pythia-1.4B.\nSelf-reference conflates the generator's distributional shift with the reference model's sensitivity; the observed attenuation may partially reflect the reference model change rather than a pure scale effect.\n\n\\paragraph{Caveats.}\nFor Qwen2.5-7B, the CI lower bound (58.0\\%) does not exclude sub-60\\% accuracy; Llama-3.1-8B's lower bound (68.3\\%) is more comfortably above chance but still below the 75--83\\% range at 1--1.5B.\nThe divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.\n\n\\paragraph{Confounds.}\n\\label{app:cross_scale_confounds}\nFive confounds limit these results: (1)~4-bit NF4 QLoRA quantization (absent at 1--1.5B) may distort the perplexity distribution independently of depth; (2)~smaller sample size (500 vs.\\ 5{,}000 per depth) widens confidence intervals; (3)~evaluation is limited to nucleus sampling, leaving other strategies untested at this scale; (4)~vocabulary mismatch between larger generators and the 1.4B reference model; (5)~Qwen2.5-14B uses self-reference rather than the Pythia-1.4B reference used for all other experiments, preventing direct cross-scale comparison at the 14B data point.\nThe base-model control partially addresses a former confound (instruction-tuning): since the base variant shows weaker signal with non-monotonic decay while the instruction-tuned variant shows stronger monotonic signal, instruction-tuning regularizes rather than confounds depth estimation.\nThe remaining confounds are not mutually independent (quantization and vocabulary mismatch both affect the perplexity distribution); it is therefore infeasible to attribute the observed accuracy gap (60--70\\% vs.\\ 78--85\\% at 1--1.5B) to any single factor.\n\n\\subsection{Cross-Boundary Generalization}\n\\label{app:cross_boundary}\n\nThe preceding experiments assume a single model family generates all recursive depths.\nIn practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.\nWe probe whether the depth signal persists under two relaxations of the single-model assumption.\n\n\\paragraph{Cross-model recursive chains.}\nWe construct a heterogeneous chain: human text (d0) $\\to$ Pythia-1.4B generates d1 $\\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.\nEach recursive step uses a \\emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.\nA 4-class Random Forest achieves 84.75\\% accuracy (95\\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).\nPairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.\nThese results suggest that distributional artifacts of recursive generation persist across model boundaries. This constitutes preliminary evidence for a process-level depth signal rather than individual generator artifacts.\n\n\\paragraph{Confound discussion.}\nThe heterogeneous chain confounds architecture identity with depth (d1=Pythia, d2=OLMo, d3=GPT-2~XL).\nHowever, if the classifier exploited architecture fingerprints rather than depth signal, near-perfect accuracy would be expected since architecture perfectly determines depth label.\nThe observed 84.75\\% with monotonically decreasing per-depth F1 (d0=0.98, d1=0.88, d2=0.76, d3=0.76) is more consistent with a depth-signal interpretation, as architecture fingerprinting would not produce this graded pattern.\nWe address this confound directly with a reverse-chain control below.\n\n\\paragraph{Reverse-chain control.}\nTo empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\\to$ OLMo $\\to$ Pythia) reversing the model-depth assignment.\nThe reverse chain achieves 85.75\\% (95\\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\\%, [81.0, 88.25]).\nIf the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.\n\n\\paragraph{Cross-domain transfer.}\nAll prior experiments use WikiText-103 as the seed corpus.\nTo test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).\nFive-fold cross-validation yields 74.1\\% $\\pm$ 2.0\\% accuracy, compared to ${\\sim}$78\\% on the WikiText seed.\nPer-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66, with d2 remaining the most challenging class.\nThe 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.\nThese results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.\n\n\\subsection{Cross-Seed Replication}\n\\label{app:seed_replication}\n\nTable~\\ref{tab:seed_replication} reports within-seed accuracy for all three model families (nucleus, depths 0--3) under two independent LoRA training seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-seed replication (nucleus $p{=}0.95$, d0--d3). seed=42 is the primary benchmark (matching Table~\\ref{tab:main_matrix}); seed=43 is an independent replication.}\n\\label{tab:seed_replication}\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\nModel & Seed & Acc (\\%) & 95\\% CI & $\\Delta$ (pp) \\\\\n\\midrule\nPythia-1.4B & 42 & 78.70 & [78.10, 79.24] & --- \\\\\nPythia-1.4B & 43 & 78.84 & [78.13, 79.52] & $+$0.14 \\\\\n\\midrule\nOLMo-1B & 42 & 78.94 & [78.38, 79.48] & --- \\\\\nOLMo-1B & 43 & 82.11 & [81.77, 82.54] & $+$3.17 \\\\\n\\midrule\nGPT-2~XL & 42 & 84.28 & [83.78, 84.80] & --- \\\\\nGPT-2~XL & 43 & 86.32 & [86.17, 86.49] & $+$2.04 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed=43 yields higher accuracy in all three models ($+$0.14 to $+$3.17\\,pp, same direction).\nFor Pythia ($+$0.14\\,pp), CIs overlap, consistent with noise; for OLMo ($+$3.17\\,pp) and GPT-2~XL ($+$2.04\\,pp), CIs do not overlap, so LoRA initialization has a non-trivial effect on absolute accuracy (${\\sim}$1--3\\,pp).\nTop-3 features are identical across all seeds and models (\\texttt{p90\\_ppl}, \\texttt{var\\_surprisal}, \\texttt{p75\\_ppl}); depth ordering is preserved in every configuration.\n\n\\paragraph{Outlier handling.}\nFeature extraction occasionally produces extreme perplexity values (outlier passages); we apply per-feature clipping at $\\pm 10^{10}$ before classification, affecting ${<}0.1$\\% of samples.\nThe d3 perplexity distribution varies substantially across seeds: under seed=42, 0.56\\% of d3 passages exceed $10^6$ in raw perplexity, while under seed=43 this fraction rises to 12.8\\%.\nDespite this variation, the classifier remains effective after clipping, confirming that the depth signal resides in the p90-and-below distributional shape rather than extreme outliers.\n\n\\subsection{Depth-4 Extension}\n\\label{app:depth4_ext}\n\nWe extend all three model families (GPT-2~XL, Pythia-1.4B, OLMo-1B; nucleus $p{=}0.95$) to depth~4 and train 5-class RF classifiers (d0--d4, 5{,}000 samples per depth).\nFive-class accuracy reaches 80.5\\% (OLMo), 74.0\\% (GPT-2~XL), and 71.3\\% (Pythia), all substantially above the 20\\% chance baseline.\nFor Pythia and GPT-2~XL, d3 recall drops from ${\\sim}$80\\% (4-class) to ${\\sim}$49\\% (5-class) due to d3/d4 confusion; d4 recall is higher (Pythia 68.1\\%, GPT-2~XL 63.9\\%).\n$\\mathrm{EDD}_{0.70} \\geq 4$ was established by dedicated binary classifiers in the atlas (\\S\\ref{sec:atlas:edd}; d3v4 AUC: Pythia 0.784, OLMo 0.765, GPT-2~XL 0.750); the 5-class results provide complementary evidence that depth~4 remains discriminable in the multi-class setting.\n\n\\paragraph{Feature monotonicity at d4.}\nFor Pythia and GPT-2~XL, the dominant depth markers (\\texttt{p90\\_ppl}, \\texttt{var\\_surprisal}) maintain monotonic decrease through d4 (Pythia \\texttt{p90\\_ppl}: $483.7 \\to 12.5$ from d0 to d4; \\texttt{var\\_surprisal}: $6.50 \\to 1.29$), consistent with continued tail erosion (\\S\\ref{sec:method:theory}).\nMean perplexity breaks monotonicity at d4 for GPT-2~XL (d3: $1{,}076\\mathrm{K}$ $\\to$ d4: $928\\mathrm{K}$) while tail perplexity continues to decline.\nOLMo exhibits a \\texttt{var\\_surprisal} rebound at d4 ($2.49 \\to 2.83$, non-monotonic), creating a feature signature absent in GPT-2~XL and Pythia.\nThe 5-class RF exploits non-adjacent depth contrasts (particularly d0-vs-d4 and d2-vs-d4) to achieve 80.5\\% accuracy, the highest among all three families, while the dedicated binary d3-vs-d4 classifier (AUC 0.765) is restricted to adjacent-depth features.\nThis discrepancy illustrates that multi-class classifiers can leverage global distributional structure unavailable to pairwise comparisons.\nThe divergence between aggregate and tail statistics suggests that aggregate distributional statistics saturate at deep recursion while tail statistics continue to shift.\nThis saturation provides a physical mechanism for the EDD ceiling: once per-step feature change falls below classifier resolution, adjacent depths become indistinguishable regardless of continued distributional drift.\n\n\\subsection{Generation Length Ablation}\n\\label{app:length_ablation}\n\nTable~\\ref{tab:length_ablation} reports classification accuracy as a function of passage length (Pythia-1.4B nucleus, depths 0--3).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Generation length ablation (Pythia-1.4B nucleus, 5-fold CV). Accuracy increases monotonically with passage length; the 9.47\\,pp spread confirms that longer passages provide stronger statistical signal.}\n\\label{tab:length_ablation}\n\\begin{tabular}{@{}lc@{}}\n\\toprule\nPassage length (tokens) & Acc (\\%) \\\\\n\\midrule\n128 & 68.35 \\\\\n256 & 73.80 \\\\\n512 & 77.82 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDepth signal is detectable from 128 tokens (2.7$\\times$ chance) and saturates near 500 tokens.\nThe monotonic increase reflects the statistical nature of the features: longer passages yield more stable estimates of perplexity percentiles and surprisal variance, reducing within-class overlap at adjacent depth boundaries.\n\n\\subsection{Mixed-Depth Corpus}\n\\label{app:mixed_depth}\n\nPer-passage classification is largely independent of corpus composition: evaluating on a corpus containing mixed proportions of d0--d3 passages (rather than balanced classes) yields macro-recall $\\Delta{=}{-}1.62$\\,pp relative to the balanced benchmark (within the 2\\,pp tolerance).\nIndividual class deltas range from $-$0.45\\,pp to $-$2.43\\,pp (d1 shows the largest shift); the RF classifier operates on per-sample features without sensitivity to the class distribution of the evaluation corpus.\nMacro-recall $\\Delta$ = $-$1.62\\,pp (within the 2\\,pp threshold); individual class variations (max 2.43\\,pp on d1) arise from held-out sample composition rather than classifier sensitivity to corpus distribution, as the Random Forest produces identical per-sample predictions regardless of batch context.\n\n\\subsection{Learned Estimator Comparison}\n\\label{app:learned_estimator}\n\nTable~\\ref{tab:learned_estimator} evaluates three learned classifiers (XGBoost, ordinal MLP with CORAL loss \\cite{coral2020}, prototypical networks) under the same leave-one-model-out protocol as Table~\\ref{tab:cross_model}.\nThe ordinal MLP follows the nested binary reduction framework \\cite{mccullagh1980_ordinal,frank2001} with the loss function of \\citet{rennie2005}.\nAll three methods operate on the same 19-dimensional feature vector; the comparison isolates the effect of the classification head.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Learned estimator cross-model transfer (leave-one-model-out, nucleus, 4-class). RF baseline from Table~\\ref{tab:cross_model}. Chance = 25\\%.}\n\\label{tab:learned_estimator}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nMethod & Pythia & OLMo & GPT-2 XL & Mean \\\\\n\\midrule\nRF (baseline) & --- & --- & --- & 66.4 \\\\\nXGBoost & 63.7 & 69.8 & 68.1 & 67.2 \\\\\nOrdinal MLP & 62.5 & 69.7 & 67.9 & 66.7 \\\\\nPrototypical & 61.6 & 70.0 & 68.4 & 66.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll three learned methods match the RF baseline within 0.8\\,pp on average; the Pythia holdout is consistently the hardest (61.6--63.7\\%), while OLMo and GPT-2~XL holdouts yield 67.9--70.0\\%.\nThe narrow spread ($\\leq$0.8\\,pp across four methods) reinforces the conclusion that the 19-feature representation, not the classifier, determines the accuracy ceiling in the cross-model transfer setting.\n\n\\subsection{Instruction-Tuned Model at 1.5B Scale}\n\\label{app:instruct_1p5b}\n\nTo test whether instruction tuning eliminates depth signal at matched scale (1.5B, avoiding the quantization confound of \\S\\ref{sec:gen:crossscale}), we run the full recursive pipeline on Qwen2.5-1.5B-Instruct with self-reference feature extraction (i.e., the same model serves as both generator and reference).\n\nThe RF classifier achieves 47.4\\% four-class accuracy (95\\% CI $[46.7, 48.1]$, $1.9\\times$ chance); instruction tuning therefore reduces but does not eliminate depth signal.\nThe pairwise AUC profile differs from base models: d0v1 = 0.653, d1v2 = 0.620, d2v3 = 0.664, with a gap-dependent pattern (non-adjacent pairs yield higher AUC, e.g., d0v3 = 0.902) but no pair reaching the 0.75 threshold.\n\nThe top-5 features shift substantially: \\texttt{surprisal\\_range}, \\texttt{surprisal\\_position\\_corr}, \\texttt{prob\\_std}, \\texttt{surprisal\\_first\\_half\\_minus\\_second}, and \\texttt{surprisal\\_std} replace the perplexity tail statistics (\\texttt{p90\\_ppl}, \\texttt{var\\_surprisal}) that dominate in base models.\nThis feature shift suggests instruction tuning compresses the perplexity distribution (reducing tail discriminability) while preserving positional and range-based surprisal patterns.\n\nTwo caveats apply: (1) self-reference evaluation may inflate or deflate accuracy relative to cross-reference evaluation (cf.\\ \\S\\ref{app:ref_ablation}); (2) a single instruction-tuned model does not establish the generality of the feature shift across architectures or instruction-tuning recipes.\n\n\\subsection{Downstream Fine-Tuning Probe}\n\\label{app:downstream}\n\nWe fine-tune Pythia-410M with LoRA ($r{=}16$, $\\alpha{=}32$) on depth-stratified subsets (500 samples each) and evaluate held-out perplexity (200 samples, 50 per depth).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Downstream fine-tuning probe: held-out perplexity by training subset (Pythia-410M LoRA, seed=42). $\\Delta$: signed difference vs.\\ baseline (negative = better).}\n\\label{tab:downstream}\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nTraining subset & PPL & $\\Delta$ vs.\\ baseline \\\\\n\\midrule\nBaseline (no fine-tuning) & 5.67 & --- \\\\\nd0 only & 5.65 & $-$0.02 \\\\\nd1 only & 5.55 & $-$0.12 \\\\\nd2 only & 5.56 & $-$0.11 \\\\\nMixed (d0--d3) & 5.55 & $-$0.12 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe hypothesis that d0-only data yields the lowest perplexity is not supported: d1-only and mixed subsets tie for best (PPL~5.55), both marginally below d0-only (5.65).\nThe PPL spread is small (0.12, 2.1\\% relative) and the sample size (500 per condition, single seed) is insufficient for statistical significance.\nTraining loss decreases monotonically with depth (d0: 2.558, d1: 1.920, d2: 1.286), consistent with recursive generation reducing information content and making text easier to model.\nThis pilot establishes that depth-filtered data is not harmful for downstream fine-tuning; whether depth-aware curation provides a meaningful advantage requires larger-scale evaluation.\n\n\\subsection{Feature Group Ablation}\n\\label{app:feature_ablation}\n\nTable~\\ref{tab:feature_ablation} reports cross-model transfer accuracy (leave-one-model-out, nucleus) when restricting the classifier to subsets of the 19-feature vector, grouped by signal type.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Feature group ablation (cross-model LOO, nucleus, 4-class). Chance = 25\\%.}\n\\label{tab:feature_ablation}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nFeature group & \\#Feat. & Acc (\\%) & $\\Delta$ vs.\\ Full \\\\\n\\midrule\nFull (all 19) & 19 & 66.6 & --- \\\\\nPerplexity only & 9 & 66.0 & $-$0.5 \\\\\nEntropy/Surprisal only & 5 & 63.2 & $-$3.4 \\\\\nRepetition/Diversity only & 5 & 53.0 & $-$13.6 \\\\\n\\midrule\n\\texttt{p90\\_ppl} only & 1 & 58.3 & $-$8.3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe 9 perplexity features nearly match the full set ($\\Delta{=}{-}0.5$\\,pp), while repetition/diversity features alone fall 13.6\\,pp below; perplexity degradation statistics therefore carry the dominant depth signal.\nThe top-2 individual features by Gini importance are \\texttt{p90\\_ppl} (22.4\\%) and \\texttt{var\\_surprisal} (18.8\\%), accounting for 41\\% of total importance.\n\n\\subsection{RF Seed Robustness}\n\\label{app:rf_seed}\n\nTable~\\ref{tab:rf_seed} reports cross-model transfer accuracy across three RF random seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{RF seed robustness (cross-model LOO, nucleus, 4-class).}\n\\label{tab:rf_seed}\n\\begin{tabular}{@{}lc@{}}\n\\toprule\nSeed & Acc (\\%) \\\\\n\\midrule\n42 & 66.4 \\\\\n123 & 66.5 \\\\\n456 & 66.5 \\\\\n\\midrule\nMean $\\pm$ std & 66.48 $\\pm$ 0.06 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe 0.06\\,pp standard deviation across seeds confirms that RF classification is deterministic to within rounding noise at this sample size, and reported accuracy differences across experimental conditions (e.g., feature ablation, cross-model transfer) are not attributable to classifier randomness.\n\n\\subsection{Binary Detector Baselines for Ordinal Classification}\n\\label{app:detector_baselines}\n\nWe evaluate whether existing binary AI-text detectors and membership inference methods, when repurposed for ordinal classification, can match our 19-feature RF pipeline.\n\n\\paragraph{Binary detectors (Pythia nucleus).}\nBinoculars~\\cite{binoculars2024} and Fast-DetectGPT~\\cite{fast_detectgpt2024} scores are computed on the Pythia-1.4B nucleus ($p{=}0.95$) subset and fed to: (a)~a log-likelihood rank classifier (Log-Rank, 64.0\\%), (b)~a combined RF trained on both detector scores (Combined, 74.2\\%), and (c)~the standard 19-feature RF (78.7\\%).\nThe 4.5\\,pp gap (74.2\\% vs.\\ 78.7\\%) confirms that perplexity distributional features capture ordinal depth structure beyond what generic detection scores provide.\nNote that Fast-DetectGPT exhibits numerical overflow on Pythia nucleus d1 (mean perturbation score $>$28{,}000); results for this cell should be interpreted cautiously.\nAcross all 9 atlas cells, Binoculars and Fast-DetectGPT ordinal accuracy averages ${\\sim}$35\\% and ${\\sim}$32\\%, respectively.\n\n\\paragraph{Membership inference baselines (all 9 cells).}\nDetectGPT~\\cite{mitchell2023_detectgpt} (gpt2-large scoring model, t5-large perturbation model, 5 perturbations) achieves 30.7\\% mean 4-class accuracy (d1--d3 BalAcc: 24.3\\%).\nMin-K\\% Prob~\\cite{shi2024_minkprob} ($K{=}20$) with CORAL ordinal calibration reaches 33.2\\% (d1--d3 BalAcc: 40.4\\%); the best single cell is gpt2xl\\_temp09 at 50.6\\%.\nMin-K\\%'s advantage over DetectGPT (+2.5\\,pp) is consistent with token-level log-probabilities containing more depth-relevant information than perturbation-based curvature, but both remain within 10\\,pp of chance.\nCORAL calibration improves ordinal structure (d1--d3 BalAcc 40.4\\% vs.\\ 33.3\\% random) without closing the gap to RF (71.6\\%), confirming that the bottleneck is the input signal rather than the calibration strategy.\nThe consistent failure of all four binary/membership methods (30--35\\% vs.\\ RF 78.4\\%) confirms that ordinal depth estimation requires depth-specific distributional features inaccessible to detection scores designed for binary classification.\n\n\\paragraph{Augmented feature set.}\nTo test whether detection scores carry complementary ordinal signal, we add Min-K\\% probability ($K{=}20$) and DetectGPT perturbation discrepancy as additional RF features.\nThe 20-feature model (19 + Min-K\\%) achieves 78.90\\% mean 4-class accuracy (+0.48\\,pp) and 72.20\\% d1--d3 balanced accuracy (+0.60\\,pp).\nMin-K\\% ranks \\#3 by feature importance (0.095), behind \\texttt{p90\\_ppl} (0.161) and \\texttt{var\\_surprisal} (0.126); DetectGPT ranks \\#17 (0.026).\nThe marginal improvement is consistent across 8 of 9 atlas cells, indicating that Min-K\\%'s token-level log-probability signal provides weak but real complementary information to the passage-level distributional features.\nThe top-2 features (\\texttt{p90\\_ppl} + \\texttt{var\\_surprisal}) retain combined importance of 28.7\\%, confirming that perplexity tail statistics remain the dominant depth markers even after augmentation.\n\n\\subsection{Prompted Generation Results}\n\\label{app:prompted_gen}\n\nTable~\\ref{tab:prompted_gen} reports depth estimation performance under topic-seeded (prompted) generation using GPT-2~XL with nucleus sampling ($p{=}0.95$, depths 0--3).\nGeneration is conditioned on Wikipedia topic prompts rather than a bare BOS token, a more ecologically valid test of depth signal persistence.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Prompted generation (GPT-2~XL, nucleus $p{=}0.95$, topic-seeded). 5-fold CV accuracy and pairwise AUC. Chance = 25\\%.}\n\\label{tab:prompted_gen}\n\\begin{tabular}{@{}lc@{}}\n\\toprule\nMetric & Value \\\\\n\\midrule\n4-class accuracy (\\%) & 69.52 $[68.9, 70.2]$ \\\\\nBOS-seeded baseline (\\%) & 83.3 \\\\\n$\\Delta$ (prompted $-$ BOS) & $-$13.78\\,pp \\\\\n\\midrule\nAUC d0v1 & 0.916 \\\\\nAUC d1v2 & 0.782 \\\\\nAUC d2v3 & 0.744 \\\\\n\\midrule\nTop-1 feature & \\texttt{p90\\_ppl} \\\\\nTop-2 feature & \\texttt{var\\_surprisal} \\\\\nTop-3 feature & \\texttt{p75\\_ppl} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe 13.8\\,pp drop relative to BOS-seeded generation is expected: topic prompts constrain the output distribution, reducing the variance that distinguishes depths.\nNevertheless, accuracy remains $2.8\\times$ chance and pairwise AUC decays monotonically (0.916, 0.782, 0.744); the depth signal is therefore not an artifact of unconstrained generation.\nTop features are identical to BOS-seeded (\\texttt{p90\\_ppl} first); the same perplexity tail erosion mechanism operates under prompted conditions.\n\n\\subsection{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Cross-strategy conditional decomposition.}\nThe two-stage pipeline (strategy identification followed by depth classification) recovers 11.5\\,pp over the na\\\"ive pooled classifier.\nUnder correct strategy routing, four-class accuracy reaches 72.6\\% vs.\\ 68.0\\% under misrouting ($N{=}103{,}498$ / $76{,}502$), a gap of 4.6\\,pp; d0 accuracy remains near-ceiling (${\\sim}99.6$\\%) regardless of routing, confirming that the d0 signal is strategy-invariant.\nEven the worst routing yields a floor of 67.6\\% ($2.7\\times$ chance), and the 31.5\\,pp d1--d3 gap between correct and wrong routing confirms feature-space misalignment rather than uniform noise.\nEnd-to-end PLMs lag RF by ${\\sim}20$\\,pp, suggesting that current pretrained representations do not capture the distributional tail statistics that drive depth discrimination.\n\n\\paragraph{Depth-graduated curation.}\nCurrent data curation operates on a binary human-vs-machine distinction \\cite{dsir2023,qurating2024}.\nRecursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.\nThe 70--85\\% in-distribution accuracy and $\\mathrm{EDD}_{0.70}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a pilot study (Appendix~\\ref{app:curation_poc}) yields an inconclusive RF-vs-unfiltered comparison ($p>0.4$), though RF-filtered subsets significantly outperform size-matched random subsampling ($p<0.001$--$0.02$); large-scale validation remains open.\nImportance weighting \\cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.\n\n\\paragraph{Toward a provenance toolkit.}\nDepth estimation complements existing provenance methods along orthogonal axes.\nWatermarking \\cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.\nSource attribution \\cite{uchendu2020_attribution} identifies the generating model but not the generation history.\nDepth estimation characterizes \\emph{iterative reuse} regardless of generator cooperation or identity.\nA layered provenance system combining these three signals (watermark presence, source model, and recursive generation depth) could support more nuanced data auditing than any single method.\n\n\\subsection{Computational Resources and Reproducibility}\n\\label{app:compute}\n\n\\paragraph{Hardware.}\nAll experiments were conducted on 2$\\times$ NVIDIA RTX PRO 6000 (48\\,GB) GPUs locally and 2$\\times$ NVIDIA RTX PRO 6000 (48\\,GB) on cloud instances.\nTotal computation is approximately 200 GPU$\\cdot$hours, covering the $3 \\times 3$ generation matrix (LoRA fine-tuning + sampling at each depth), feature extraction, depth extension to d5, 7--14B QLoRA experiments, and all ablations.\n\n\\paragraph{Software.}\nKey library versions: PyTorch 2.10.0+cu128, Transformers 5.8.1, PEFT 0.7.1, scikit-learn 1.8.0.\nAdditional dependencies: Accelerate 1.13.0, Datasets 4.8.4, XGBoost 3.2.0, NumPy 2.2.6 (Python 3.12.3, CUDA 12.8).\n\n\\paragraph{Hyperparameters.}\nLoRA hyperparameters ($r{=}16$, $\\alpha{=}32$, dropout $0.05$, lr $2{\\times}10^{-4}$, batch size 8, 3 epochs) follow \\citet{hu2022lora}.\nThe Random Forest classifier uses 200 trees, Gini criterion, and no max depth, without hyperparameter search; all reported results use 5-fold stratified cross-validation.\n\n\\paragraph{Inference cost.}\nFeature extraction and classification require no GPU.\nInference takes approximately 2 minutes per 5{,}000 samples on a single CPU core (reference-model forward pass + RF prediction), enabling deployment without specialized hardware.\n",
      "numLines": 806,
      "startLine": 1,
      "totalLines": 806
    }
  },
  "sourceToolAssistantUUID": "b37c39a3-a88d-435f-8238-19ed2ce96ebd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 56 · 2026-05-19T02:59:05.455Z_

<details open><summary>🔧 Tool call — WebSearch · `toolu_017zJN78bNE3J6ubMHNdRkcK`</summary>

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
  "parentUuid": "88ba207b-bd87-47a4-9fad-82e8a2b65134",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "c038baa7-0212-4152-acf7-d1414e7bee04",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 57 · 2026-05-19T02:59:05.980Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__verify_references · `toolu_015jUowEUHRVxwKP1QHqw2hZ`</summary>

```json
{
  "paper_dir": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c038baa7-0212-4152-acf7-d1414e7bee04",
  "isSidechain": false,
  "requestId": "req_011CbBBKsZFKQQ4WcFxSeV2a",
  "type": "assistant",
  "uuid": "7889b7fa-9618-4b72-a19d-6d58105af255",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3YAZCcRyRfTiU6fCXmB1U",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 506,
      "cache_read_input_tokens": 34077,
      "output_tokens": 896,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 506,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 896,
          "cache_read_input_tokens": 34077,
          "cache_creation_input_tokens": 506,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 506
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

_source line 58_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**  ### Venue 信息 - **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿) - **截止日期**：2026-05-25 - **页数限制**：Long paper 8 pag…",
  "leafUuid": "7889b7fa-9618-4b72-a19d-6d58105af255",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Runtime record

_source line 59_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Tool result

_source line 60 · 2026-05-19T02:59:23.904Z_

<details><summary>↩ Tool result · `toolu_017zJN78bNE3J6ubMHNdRkcK`</summary>

```text
Web search results for query: "ACL ARR 2025 2026 reviewer guidelines review form criteria scoring"

Links: [{"title":"ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewerguidelines"},{"title":"ARR Area Chair Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/acguidelines"},{"title":"aclrollingreview/cfp.md at main · acl-org/aclrollingreview","url":"https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"},{"title":"CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/cfp"},{"title":"Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/authors"},{"title":"ACLRollingReview (@ReviewAcl) / X","url":"https://x.com/reviewacl"},{"title":"ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"https://aclrollingreview.org/"}]

Based on the search results, here is information about ACL ARR 2025-2026 reviewer guidelines, review form criteria, and scoring:

## Review Scoring Criteria

Starting with February 2025, ARR reviewers are asked to provide three scores: soundness, excitement, and overall recommendation.

### Soundness Score
Soundness scores must be justified by the text of the review. If you give a low Soundness score without finding any major faults, this means that your review is not a faithful explanation of your recommendation, and you need to revise it.

### Excitement Score
Sometimes you may find the work sound, but not something that is interesting for you personally. Such preferences are more subjective and should be reflected in a separate excitement score, which is orthogonal to the assessment of the soundness of the paper.

## Review Requirements

All reviewers must familiarize themselves with the latest version of the ARR reviewer guidelines and perform the reviews on time and in line with ARR requirements.

The official ARR Reviewer Guidelines are available at http://aclrollingreview.org/reviewerguidelines for more comprehensive details on the review form and scoring criteria.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c038baa7-0212-4152-acf7-d1414e7bee04",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "77e1ba07-b48c-4de1-9942-100bfe4da12a",
  "toolUseResult": {
    "query": "ACL ARR 2025 2026 reviewer guidelines review form criteria scoring",
    "results": [
      {
        "tool_use_id": "srvtoolu_01Py543a2NS5Lj9AuvXb8NrW",
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
            "title": "aclrollingreview/cfp.md at main · acl-org/aclrollingreview",
            "url": "https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"
          },
          {
            "title": "CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/cfp"
          },
          {
            "title": "Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/authors"
          },
          {
            "title": "ACLRollingReview (@ReviewAcl) / X",
            "url": "https://x.com/reviewacl"
          },
          {
            "title": "ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "https://aclrollingreview.org/"
          }
        ]
      },
      "Based on the search results, here is information about ACL ARR 2025-2026 reviewer guidelines, review form criteria, and scoring:\n\n## Review Scoring Criteria\n\nStarting with February 2025, ARR reviewers are asked to provide three scores: soundness, excitement, and overall recommendation.\n\n### Soundness Score\nSoundness scores must be justified by the text of the review. If you give a low Soundness score without finding any major faults, this means that your review is not a faithful explanation of your recommendation, and you need to revise it.\n\n### Excitement Score\nSometimes you may find the work sound, but not something that is interesting for you personally. Such preferences are more subjective and should be reflected in a separate excitement score, which is orthogonal to the assessment of the soundness of the paper.\n\n## Review Requirements\n\nAll reviewers must familiarize themselves with the latest version of the ARR reviewer guidelines and perform the reviews on time and in line with ARR requirements.\n\nThe official ARR Reviewer Guidelines are available at http://aclrollingreview.org/reviewerguidelines for more comprehensive details on the review form and scoring criteria."
    ],
    "durationSeconds": 18.443589915999997
  },
  "sourceToolAssistantUUID": "c038baa7-0212-4152-acf7-d1414e7bee04",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 61 · 2026-05-19T03:00:17.593Z_

<details><summary>↩ Tool result · `toolu_015jUowEUHRVxwKP1QHqw2hZ`</summary>

```text
&lt;persisted-output>
Output too large (53.1KB). Full output saved to: /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-review-reviewer-1-37084335/18e2781e-e5ad-47ad-895c-aafdbd2b04f0/tool-results/toolu_015jUowEUHRVxwKP1QHqw2hZ.txt

Preview (first 2KB):
{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 68, \"total_citations\": 102, \"unique_cited_keys\": 67, \"orphan_bib\": 1, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 56, \"online_not_found\": 7, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [\"c2pa2024\"], \"missing_bib\": [], \"orphan_count\": 1, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"shumailov2024_nature\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"type\": \"inproceedings\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"dohmatob2024_demystified\", \"type\": \"inproceedings\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"alemohammad2024_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"type\": \"misc\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerst
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7889b7fa-9618-4b72-a19d-6d58105af255",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "1a104516-e8fc-4910-aec7-9350177b5cab",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 68, \\\"total_citations\\\": 102, \\\"unique_cited_keys\\\": 67, \\\"orphan_bib\\\": 1, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 56, \\\"online_not_found\\\": 7, \\\"online_mismatch\\\": 5}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [\\\"c2pa2024\\\"], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 1, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"authors\\\": \\\"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICASSP\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\\\", \\\"authors\\\": \\\"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"authors\\\": \\\"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"authors\\\": \\\"Schaffelder, Max and Gatt, Albert\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"authors\\\": \\\"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"authors\\\": \\\"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"3rd DATA-FM Workshop at ICLR 2026\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"authors\\\": \\\"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Findings of EMNLP\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\\\", \\\"authors\\\": \\\"Bakshi, Soham and Chakraborty, Sunrit\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\\\", \\\"authors\\\": \\\"Wang, Kevin and Niu, Hongqian and Li, Didong\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\\\", \\\"authors\\\": \\\"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of ACL: System Demonstrations\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research (TMLR)\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"authors\\\": \\\"Pudasaini, Shushanta and Miralles-Pech\\\\\\\\'uan, Luis and Lillis, David and Llorens ...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"authors\\\": \\\"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of EMNLP\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"authors\\\": \\\"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"tulchinskii2023_intrinsic_dim\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"authors\\\": \\\"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NAACL\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\\\"}, {\\\"key\\\": \\\"li2024_mage\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"MAGE: Machine-generated Text Detection in the Wild\\\", \\\"authors\\\": \\\"Li, Yongkang and Li, Donghao and Yang, Yue and Hu, Baotian and Zhang, Min\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"authors\\\": \\\"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of COLING\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"authors\\\": \\\"Wiher, Gian and Meister, Clara and Cotterell, Ryan\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Transactions of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"authors\\\": \\\"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"authors\\\": \\\"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of CVPR\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"authors\\\": \\\"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"authors\\\": \\\"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"RoBERTa: A Robustly Optimized BERT Pretraining Approach\\\", \\\"authors\\\": \\\"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"penedo2024_fineweb\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"authors\\\": \\\"\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"authors\\\": \\\"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\\\\\\\\\"uller, Klaus-Robert\\\", \\\"year\\\": \\\"2007\\\", \\\"venue\\\": \\\"Journal of Machine Learning Research\\\"}, {\\\"key\\\": \\\"c2pa2024\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"C2PA Specification: Coalition for Content Provenance and Authenticity\\\", \\\"authors\\\": \\\"C2PA\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Qwen2.5: A Party of Foundation Models\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"authors\\\": \\\"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of ECML\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\\\", \\\"authors\\\": \\\"Rennie, Jason D. M. and Srebro, Nathan\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of IJCAI Workshop on Advances in Preference Handling\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"authors\\\": \\\"McCullagh, Peter\\\", \\\"year\\\": \\\"1980\\\", \\\"venue\\\": \\\"Journal of the Royal Statistical Society: Series B\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of LREC\\\"}, {\\\"key\\\": \\\"dugan2024_raid\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"authors\\\": \\\"Dugan, Liam and Hwang, Alyssa and Trhl\\\\\\\\'\\\\\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of NAACL\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"authors\\\": \\\"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"authors\\\": \\\"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"janitza2016_ordinal_rf\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Random Forest for Ordinal Responses: Prediction and Variable Selection\\\", \\\"authors\\\": \\\"Janitza, Silke and Tutz, Gerhard and Boulesteix, Anne-Laure\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Computational Statistics \\\\\\\\& Data Analysis\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"authors\\\": \\\"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"christ2024_undetectable\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"authors\\\": \\\"Christ, Miranda and Gunn, Sam and Zamir, Or\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of COLT\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"On the Stability of Iterative Retraining of Generative Models on their own Data\\\", \\\"authors\\\": \\\"Bertrand, Quentin and Bose, Avishek Joey and Duplessis, Alexandre and Jiralerspo...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"guo2024_biscope\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\\\", \\\"authors\\\": \\\"Guo, Hanxi and Cheng, Siyuan and Jin, Xiaolong and Zhang, Zhuo and Zhang, Kaiyua...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"kasa2024_ordinality\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\\\", \\\"authors\\\": \\\"Kasa, Siva Rajesh and Goel, Aniket and Gupta, Karan and Roychowdhury, Sumegh and...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"guo2024_biscope\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"tulchinskii2023_intrinsic_dim\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dugan2024_raid\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"li2024_mage\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"christ2024_undetectable\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kasa2024_ordinality\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"janitza2016_ordinal_rf\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 33, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 104, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 104, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"theory.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"theory.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"file\\\": \\\"theory.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"atlas.tex\\\", \\\"line\\\": 56, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"atlas.tex\\\", \\\"line\\\": 126, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 114, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 114, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"penedo2024_fineweb\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 35, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 57, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 57, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 207, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 207, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 234, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 590, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 591, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 591, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 591, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 713, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 713, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 719, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 720, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 776, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 776, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 779, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 783, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 784, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 800, \\\"command\\\": \\\"citet\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"title\\\": \\\"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.288, \\\"matched_title\\\": \\\"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.29 below threshold 0.82\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"title\\\": \\\"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.0, \\\"matched_title\\\": \\\"\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"no results from OpenAlex\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"tulchinskii2023_intrinsic_dim\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"li2024_mage\\\", \\\"title\\\": \\\"MAGE: Machine-generated Text Detection in the Wild\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MAGE: Machine-generated Text Detection in the Wild\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=garces arias vs api=arias\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"matched_year\\\": \\\"2022\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [\\\"year: bib=2023 vs api=2021\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"title\\\": \\\"RoBERTa: A Robustly Optimized BERT Pretraining Approach\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.495, \\\"matched_title\\\": \\\"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"penedo2024_fineweb\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"matched_year\\\": \\\"2007\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"c2pa2024\\\", \\\"title\\\": \\\"C2PA Specification: Coalition for Content Provenance and Authenticity\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.409, \\\"matched_title\\\": \\\"Integrating Content Authenticity with DASH Video Streaming\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.41 below threshold 0.82\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"title\\\": \\\"Qwen2.5: A Party of Foundation Models\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.333, \\\"matched_title\\\": \\\"Can Open Large Language Models Catch Vulnerabilities?\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.33 below threshold 0.82\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"title\\\": \\\"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.373, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.37 below threshold 0.82\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"matched_year\\\": \\\"1980\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dugan2024_raid\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"janitza2016_ordinal_rf\\\", \\\"title\\\": \\\"Random Forest for Ordinal Responses: Prediction and Variable Selection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Random forest for ordinal responses: Prediction and variable selection\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"christ2024_undetectable\\\", \\\"title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"title\\\": \\\"On the Stability of Iterative Retraining of Generative Models on their own Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"On the Stability of Iterative Retraining of Generative Models on their own Data\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"guo2024_biscope\\\", \\\"title\\\": \\\"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=guo vs api=cheng\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"kasa2024_ordinality\\\", \\\"title\\\": \\\"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 68, \"total_citations\": 102, \"unique_cited_keys\": 67, \"orphan_bib\": 1, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 56, \"online_not_found\": 7, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [\"c2pa2024\"], \"missing_bib\": [], \"orphan_count\": 1, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"shumailov2024_nature\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"type\": \"inproceedings\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"dohmatob2024_demystified\", \"type\": \"inproceedings\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"alemohammad2024_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"type\": \"misc\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"type\": \"inproceedings\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"authors\": \"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\", \"year\": \"2024\", \"venue\": \"Proceedings of ICASSP\"}, {\"key\": \"knowledge_collapse2025\", \"type\": \"misc\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"authors\": \"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"sigma2026_spectral\", \"type\": \"misc\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"authors\": \"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"synthetic_eggs2026\", \"type\": \"inproceedings\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"authors\": \"Schaffelder, Max and Gatt, Albert\", \"year\": \"2026\", \"venue\": \"Findings of ACL\"}, {\"key\": \"shi2025_closer_look\", \"type\": \"inproceedings\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"authors\": \"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\", \"year\": \"2025\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"yi2026_escaping_collapse\", \"type\": \"inproceedings\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"authors\": \"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\", \"year\": \"2026\", \"venue\": \"3rd DATA-FM Workshop at ICLR 2026\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"type\": \"inproceedings\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"authors\": \"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\", \"year\": \"2025\", \"venue\": \"Findings of EMNLP\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"type\": \"misc\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\", \"authors\": \"Bakshi, Soham and Chakraborty, Sunrit\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wang2026_contamination\", \"type\": \"misc\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\", \"authors\": \"Wang, Kevin and Niu, Hongqian and Li, Didong\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"falahati2026_curated\", \"type\": \"misc\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\", \"authors\": \"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wu2025_detection_survey\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"gehrmann2019_gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of ACL: System Demonstrations\"}, {\"key\": \"mitchell2023_detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"fast_detectgpt2024\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"binoculars2024\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"diveye2026\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research (TMLR)\"}, {\"key\": \"sadasivan2023_paraphrase\", \"type\": \"misc\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2023\", \"venue\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"type\": \"misc\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"authors\": \"Pudasaini, Shushanta and Miralles-Pech\\\\'uan, Luis and Lillis, David and Llorens ...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"type\": \"misc\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"type\": \"inproceedings\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"authors\": \"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\", \"year\": \"2025\", \"venue\": \"Findings of ACL\"}, {\"key\": \"uchendu2020_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of EMNLP\"}, {\"key\": \"editlens2026\", \"type\": \"inproceedings\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"authors\": \"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\", \"year\": \"2026\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"tulchinskii2023_intrinsic_dim\", \"type\": \"inproceedings\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"authors\": \"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\", \"year\": \"2023\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"verma2024_ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of NAACL\"}, {\"key\": \"wang2024_m4_semeval\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\"}, {\"key\": \"li2024_mage\", \"type\": \"inproceedings\", \"title\": \"MAGE: Machine-generated Text Detection in the Wild\", \"authors\": \"Li, Yongkang and Li, Donghao and Yang, Yue and Hu, Baotian and Zhang, Min\", \"year\": \"2024\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"yang2024_dnagpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"kirchenbauer2023_watermark\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"holtzman2020_nucleus\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"finlayson2024_closing\", \"type\": \"inproceedings\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"authors\": \"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"type\": \"inproceedings\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"authors\": \"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\", \"year\": \"2025\", \"venue\": \"Proceedings of COLING\"}, {\"key\": \"wiher2022_decoding\", \"type\": \"article\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"authors\": \"Wiher, Gian and Meister, Clara and Cotterell, Ryan\", \"year\": \"2022\", \"venue\": \"Transactions of the Association for Computational Linguistics\"}, {\"key\": \"basu2021_mirostat\", \"type\": \"inproceedings\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"authors\": \"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\", \"year\": \"2021\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"coral2020\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"cloc2025\", \"type\": \"inproceedings\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"authors\": \"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\", \"year\": \"2025\", \"venue\": \"Proceedings of CVPR\"}, {\"key\": \"hu2022lora\", \"type\": \"inproceedings\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"authors\": \"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\", \"year\": \"2022\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"he2021_deberta_v3\", \"type\": \"inproceedings\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"authors\": \"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\", \"year\": \"2023\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"liu2019_roberta\", \"type\": \"misc\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"authors\": \"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\", \"year\": \"2019\", \"venue\": \"\"}, {\"key\": \"dsir2023\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"qurating2024\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"penedo2024_fineweb\", \"type\": \"inproceedings\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"authors\": \"\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"type\": \"article\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"authors\": \"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\"uller, Klaus-Robert\", \"year\": \"2007\", \"venue\": \"Journal of Machine Learning Research\"}, {\"key\": \"c2pa2024\", \"type\": \"misc\", \"title\": \"C2PA Specification: Coalition for Content Provenance and Authenticity\", \"authors\": \"C2PA\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"qwen2.5\", \"type\": \"misc\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"llama3\", \"type\": \"misc\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"schaeffer2025\", \"type\": \"misc\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"authors\": \"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"frank2001\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of ECML\"}, {\"key\": \"rennie2005\", \"type\": \"inproceedings\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"authors\": \"Rennie, Jason D. M. and Srebro, Nathan\", \"year\": \"2005\", \"venue\": \"Proceedings of IJCAI Workshop on Advances in Preference Handling\"}, {\"key\": \"mccullagh1980_ordinal\", \"type\": \"article\", \"title\": \"Regression Models for Ordinal Data\", \"authors\": \"McCullagh, Peter\", \"year\": \"1980\", \"venue\": \"Journal of the Royal Statistical Society: Series B\"}, {\"key\": \"wenzek2020_ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of LREC\"}, {\"key\": \"dugan2024_raid\", \"type\": \"inproceedings\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"authors\": \"Dugan, Liam and Hwang, Alyssa and Trhl\\\\'\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\", \"year\": \"2024\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"guo2024curious\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of NAACL\"}, {\"key\": \"padmakumar2024diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"briesch2024selfconsuming\", \"type\": \"misc\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"authors\": \"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"seddik2024synthetic\", \"type\": \"misc\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"authors\": \"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"janitza2016_ordinal_rf\", \"type\": \"article\", \"title\": \"Random Forest for Ordinal Responses: Prediction and Variable Selection\", \"authors\": \"Janitza, Silke and Tutz, Gerhard and Boulesteix, Anne-Laure\", \"year\": \"2016\", \"venue\": \"Computational Statistics \\\\& Data Analysis\"}, {\"key\": \"shi2024_minkprob\", \"type\": \"inproceedings\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"authors\": \"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"christ2024_undetectable\", \"type\": \"inproceedings\", \"title\": \"Undetectable Watermarks for Language Models\", \"authors\": \"Christ, Miranda and Gunn, Sam and Zamir, Or\", \"year\": \"2024\", \"venue\": \"Proceedings of COLT\"}, {\"key\": \"bertrand2024_stability\", \"type\": \"inproceedings\", \"title\": \"On the Stability of Iterative Retraining of Generative Models on their own Data\", \"authors\": \"Bertrand, Quentin and Bose, Avishek Joey and Duplessis, Alexandre and Jiralerspo...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"guo2024_biscope\", \"type\": \"inproceedings\", \"title\": \"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\", \"authors\": \"Guo, Hanxi and Cheng, Siyuan and Jin, Xiaolong and Zhang, Zhuo and Zhang, Kaiyua...\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"kasa2024_ordinality\", \"type\": \"inproceedings\", \"title\": \"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\", \"authors\": \"Kasa, Siva Rajesh and Goel, Aniket and Gupta, Karan and Roychowdhury, Sumegh and...\", \"year\": \"2024\", \"venue\": \"Findings of ACL\"}], \"tex_citations\": [{\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"citet\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"seddik2024synthetic\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"bertrand2024_stability\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"citet\"}, {\"key\": \"shi2025_closer_look\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"citet\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"citet\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"yi2026_escaping_collapse\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"wenzek2020_ccnet\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"marchi2024_heat_death\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"wang2026_contamination\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"knowledge_collapse2025\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_demystified\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"guo2024curious\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"briesch2024selfconsuming\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"padmakumar2024diversity\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"sigma2026_spectral\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"synthetic_eggs2026\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"schaeffer2025\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"wu2025_detection_survey\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"guo2024_biscope\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"gehrmann2019_gltr\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"verma2024_ghostbuster\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"yang2024_dnagpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"tulchinskii2023_intrinsic_dim\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pu2026_generator_barrier\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"wang2024_m4_semeval\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"dugan2024_raid\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"li2024_mage\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"citet\"}, {\"key\": \"shi2024_minkprob\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"christ2024_undetectable\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"editlens2026\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"mohamed2025_broken_telephone\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"coral2020\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"kasa2024_ordinality\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"citet\"}, {\"key\": \"janitza2016_ordinal_rf\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"citet\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"finlayson2024_closing\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"wiher2022_decoding\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"basu2021_mirostat\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"method.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"hu2022lora\", \"file\": \"method.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"theory.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"theory.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"bertrand2024_stability\", \"file\": \"theory.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 56, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 126, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shi2024_minkprob\", \"file\": \"generalization.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"generalization.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"generalization.tex\", \"line\": 114, \"command\": \"cite\"}, {\"key\": \"qwen2.5\", \"file\": \"generalization.tex\", \"line\": 114, \"command\": \"cite\"}, {\"key\": \"penedo2024_fineweb\", \"file\": \"conclusion.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"conclusion.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"conclusion.tex\", \"line\": 35, \"command\": \"citet\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"conclusion.tex\", \"line\": 57, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"conclusion.tex\", \"line\": 57, \"command\": \"cite\"}, {\"key\": \"he2021_deberta_v3\", \"file\": \"section_appendix.tex\", \"line\": 207, \"command\": \"cite\"}, {\"key\": \"liu2019_roberta\", \"file\": \"section_appendix.tex\", \"line\": 207, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"section_appendix.tex\", \"line\": 234, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"section_appendix.tex\", \"line\": 590, \"command\": \"cite\"}, {\"key\": \"mccullagh1980_ordinal\", \"file\": \"section_appendix.tex\", \"line\": 591, \"command\": \"cite\"}, {\"key\": \"frank2001\", \"file\": \"section_appendix.tex\", \"line\": 591, \"command\": \"cite\"}, {\"key\": \"rennie2005\", \"file\": \"section_appendix.tex\", \"line\": 591, \"command\": \"citet\"}, {\"key\": \"binoculars2024\", \"file\": \"section_appendix.tex\", \"line\": 713, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"section_appendix.tex\", \"line\": 713, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"section_appendix.tex\", \"line\": 719, \"command\": \"cite\"}, {\"key\": \"shi2024_minkprob\", \"file\": \"section_appendix.tex\", \"line\": 720, \"command\": \"cite\"}, {\"key\": \"dsir2023\", \"file\": \"section_appendix.tex\", \"line\": 776, \"command\": \"cite\"}, {\"key\": \"qurating2024\", \"file\": \"section_appendix.tex\", \"line\": 776, \"command\": \"cite\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"file\": \"section_appendix.tex\", \"line\": 779, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"section_appendix.tex\", \"line\": 783, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"section_appendix.tex\", \"line\": 784, \"command\": \"cite\"}, {\"key\": \"hu2022lora\", \"file\": \"section_appendix.tex\", \"line\": 800, \"command\": \"citet\"}], \"online_verification\": [{\"key\": \"shumailov2024_nature\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_demystified\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Model Collapse Demystified: The Case of Regression\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"alemohammad2024_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"knowledge_collapse2025\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"status\": \"not_found\", \"confidence\": 0.288, \"matched_title\": \"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.29 below threshold 0.82\"}, {\"key\": \"sigma2026_spectral\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthetic_eggs2026\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shi2025_closer_look\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yi2026_escaping_collapse\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Machine-generated text detection prevents language model collapse\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2026_contamination\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"falahati2026_curated\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\", \"status\": \"not_found\", \"confidence\": 0.0, \"matched_title\": \"\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"no results from OpenAlex\"}, {\"key\": \"wu2025_detection_survey\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gehrmann2019_gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mitchell2023_detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"fast_detectgpt2024\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars2024\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye2026\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sadasivan2023_paraphrase\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can AI-Generated Text be Reliably Detected?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu2020_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"editlens2026\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"tulchinskii2023_intrinsic_dim\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"verma2024_ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2024_m4_semeval\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"li2024_mage\", \"title\": \"MAGE: Machine-generated Text Detection in the Wild\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MAGE: Machine-generated Text Detection in the Wild\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yang2024_dnagpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"kirchenbauer2023_watermark\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"holtzman2020_nucleus\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"finlayson2024_closing\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Closing the Curious Case of Neural Text Degeneration\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=garces arias vs api=arias\"], \"note\": \"\"}, {\"key\": \"wiher2022_decoding\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On Decoding Strategies for Neural Text Generators\", \"matched_year\": \"2022\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"basu2021_mirostat\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"coral2020\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cloc2025\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"hu2022lora\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"he2021_deberta_v3\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"matched_year\": \"2021\", \"mismatch_fields\": [\"year: bib=2023 vs api=2021\"], \"note\": \"\"}, {\"key\": \"liu2019_roberta\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"status\": \"not_found\", \"confidence\": 0.495, \"matched_title\": \"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"dsir2023\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating2024\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"penedo2024_fineweb\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"matched_year\": \"2007\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"c2pa2024\", \"title\": \"C2PA Specification: Coalition for Content Provenance and Authenticity\", \"status\": \"not_found\", \"confidence\": 0.409, \"matched_title\": \"Integrating Content Authenticity with DASH Video Streaming\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.41 below threshold 0.82\"}, {\"key\": \"qwen2.5\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"status\": \"not_found\", \"confidence\": 0.333, \"matched_title\": \"Can Open Large Language Models Catch Vulnerabilities?\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.33 below threshold 0.82\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"schaeffer2025\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Position: Model Collapse Does Not Mean What You Think\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank2001\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"rennie2005\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"status\": \"not_found\", \"confidence\": 0.373, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.37 below threshold 0.82\"}, {\"key\": \"mccullagh1980_ordinal\", \"title\": \"Regression Models for Ordinal Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Regression Models for Ordinal Data\", \"matched_year\": \"1980\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wenzek2020_ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dugan2024_raid\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"guo2024curious\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"padmakumar2024diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"briesch2024selfconsuming\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"seddik2024synthetic\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"janitza2016_ordinal_rf\", \"title\": \"Random Forest for Ordinal Responses: Prediction and Variable Selection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Random forest for ordinal responses: Prediction and variable selection\", \"matched_year\": \"2015\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shi2024_minkprob\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Detecting Pretraining Data from Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"christ2024_undetectable\", \"title\": \"Undetectable Watermarks for Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Undetectable Watermarks for Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bertrand2024_stability\", \"title\": \"On the Stability of Iterative Retraining of Generative Models on their own Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On the Stability of Iterative Retraining of Generative Models on their own Data\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"guo2024_biscope\", \"title\": \"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=guo vs api=cheng\"], \"note\": \"\"}, {\"key\": \"kasa2024_ordinality\", \"title\": \"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "7889b7fa-9618-4b72-a19d-6d58105af255",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 62 · 2026-05-19T03:00:17.611Z_

```json
{
  "parentUuid": "1a104516-e8fc-4910-aec7-9350177b5cab",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "in_progress",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "pending",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "pending",
        "activeForm": "验证引用"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "pending",
        "activeForm": "撰写审稿意见"
      }
    ],
    "itemCount": 4
  },
  "type": "attachment",
  "uuid": "3c63fb70-4fd9-4dbc-bf8c-c3de56adecc1",
  "timestamp": "2026-05-19T03:00:17.611Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 63_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**  ### Venue 信息 - **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿) - **截止日期**：2026-05-25 - **页数限制**：Long paper 8 pag…",
  "leafUuid": "3c63fb70-4fd9-4dbc-bf8c-c3de56adecc1",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Runtime record

_source line 64_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Assistant

_source line 65 · 2026-05-19T03:00:25.484Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the full reference verification results and the ARR reviewer guidelines in detail.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c63fb70-4fd9-4dbc-bf8c-c3de56adecc1",
  "isSidechain": false,
  "requestId": "req_011CbBBRvw4qZfUSwRzWbpV1",
  "type": "assistant",
  "uuid": "eca0c1d9-ad9d-43ec-8ae9-1f94926f947a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbSHs9N5gB94NSiap4iSTq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 63929,
      "cache_read_input_tokens": 11841,
      "output_tokens": 339,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 63929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 339,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 63929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 63929
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

_source line 66 · 2026-05-19T03:00:26.956Z_

需要详细了解 ARR review form 的评分维度。同时读取引用验证的完整结果。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eca0c1d9-ad9d-43ec-8ae9-1f94926f947a",
  "isSidechain": false,
  "requestId": "req_011CbBBRvw4qZfUSwRzWbpV1",
  "type": "assistant",
  "uuid": "8f80d085-4a53-4870-ada1-28125cc8daf1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbSHs9N5gB94NSiap4iSTq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 63929,
      "cache_read_input_tokens": 11841,
      "output_tokens": 339,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 63929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 339,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 63929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 63929
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

_source line 67 · 2026-05-19T03:00:28.524Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01FdrDH1vJJiiWV5L1s8Mct6`</summary>

```json
{
  "todos": [
    {
      "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
      "status": "completed",
      "activeForm": "搜索 ACL ARR reviewer guidelines"
    },
    {
      "content": "通读论文全文（所有章节）",
      "status": "completed",
      "activeForm": "通读论文全文"
    },
    {
      "content": "验证引用完整性和真实性",
      "status": "in_progress",
      "activeForm": "验证引用完整性和真实性"
    },
    {
      "content": "撰写审稿意见并汇报 Director",
      "status": "pending",
      "activeForm": "撰写审稿意见"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8f80d085-4a53-4870-ada1-28125cc8daf1",
  "isSidechain": false,
  "requestId": "req_011CbBBRvw4qZfUSwRzWbpV1",
  "type": "assistant",
  "uuid": "49c813e7-94b8-4397-9020-845a881fba75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbSHs9N5gB94NSiap4iSTq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 63929,
      "cache_read_input_tokens": 11841,
      "output_tokens": 339,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 63929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 339,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 63929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 63929
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

_source line 68 · 2026-05-19T03:00:29.173Z_

<details><summary>↩ Tool result · `toolu_01KVTDUXkurexjUwngc2MN5A`</summary>

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
  "parentUuid": "31e21cb2-968d-48b4-a869-4c7414705321",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "4c3959ab-78ba-4c22-94ac-c3374336019f",
  "toolUseResult": {
    "matches": [
      "WebFetch"
    ],
    "query": "select:WebFetch",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "31e21cb2-968d-48b4-a869-4c7414705321",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 69 · 2026-05-19T03:00:28.530Z_

<details><summary>↩ Tool result · `toolu_01FdrDH1vJJiiWV5L1s8Mct6`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "49c813e7-94b8-4397-9020-845a881fba75",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "53eb867b-873d-43fd-ab89-63a30f192dc6",
  "toolUseResult": {
    "oldTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "in_progress",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "pending",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "pending",
        "activeForm": "验证引用"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "pending",
        "activeForm": "撰写审稿意见"
      }
    ],
    "newTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "completed",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "completed",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "in_progress",
        "activeForm": "验证引用完整性和真实性"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "pending",
        "activeForm": "撰写审稿意见"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "49c813e7-94b8-4397-9020-845a881fba75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 70 · 2026-05-19T03:00:29.169Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01KVTDUXkurexjUwngc2MN5A`</summary>

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
  "parentUuid": "53eb867b-873d-43fd-ab89-63a30f192dc6",
  "isSidechain": false,
  "requestId": "req_011CbBBRvw4qZfUSwRzWbpV1",
  "type": "assistant",
  "uuid": "31e21cb2-968d-48b4-a869-4c7414705321",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbSHs9N5gB94NSiap4iSTq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 63929,
      "cache_read_input_tokens": 11841,
      "output_tokens": 339,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 63929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 339,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 63929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 63929
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

_source line 71 · 2026-05-19T03:00:37.480Z_

<details open><summary>🔧 Tool call — WebFetch · `toolu_01VKm9Jj5UMQXiXLUct72dYb`</summary>

```json
{
  "url": "https://aclrollingreview.org/reviewerguidelines",
  "prompt": "Extract the complete review form criteria, scoring dimensions, and their scales. I need: 1) All scoring dimensions (soundness, excitement, overall assessment, etc.) and their scales (1-5? 1-6?). 2) What each score level means. 3) Any other required fields in the review form (confidence, reproducibility, etc.). 4) Guidelines on what constitutes a good vs bad review."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4c3959ab-78ba-4c22-94ac-c3374336019f",
  "isSidechain": false,
  "requestId": "req_011CbBBSniVKaMGKmNshNotC",
  "type": "assistant",
  "uuid": "4b6b850f-b506-4049-b99c-712c7edd4f58",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MSdXff5Sui1WeSj1u6YwD4",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1146,
      "cache_read_input_tokens": 75770,
      "output_tokens": 320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1146,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 320,
          "cache_read_input_tokens": 75770,
          "cache_creation_input_tokens": 1146,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1146
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

_source line 72 · 2026-05-19T03:00:40.628Z_

<details open><summary>🔧 Tool call — Read · `toolu_01VNVtpVVTTHXSJKx422PfxU`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-review-reviewer-1-37084335/18e2781e-e5ad-47ad-895c-aafdbd2b04f0/tool-results/toolu_015jUowEUHRVxwKP1QHqw2hZ.txt"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4b6b850f-b506-4049-b99c-712c7edd4f58",
  "isSidechain": false,
  "requestId": "req_011CbBBSniVKaMGKmNshNotC",
  "type": "assistant",
  "uuid": "d38d6eb0-e71d-45a1-ac9d-5621edd436fa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MSdXff5Sui1WeSj1u6YwD4",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1146,
      "cache_read_input_tokens": 75770,
      "output_tokens": 320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1146,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 320,
          "cache_read_input_tokens": 75770,
          "cache_creation_input_tokens": 1146,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1146
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

_source line 73 · 2026-05-19T03:00:41.120Z_

<details><summary>↩ Tool result · `toolu_01VNVtpVVTTHXSJKx422PfxU`</summary>

```text
1	{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 68, \"total_citations\": 102, \"unique_cited_keys\": 67, \"orphan_bib\": 1, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 56, \"online_not_found\": 7, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [\"c2pa2024\"], \"missing_bib\": [], \"orphan_count\": 1, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"shumailov2024_nature\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"type\": \"inproceedings\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"dohmatob2024_demystified\", \"type\": \"inproceedings\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"alemohammad2024_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"type\": \"misc\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"type\": \"inproceedings\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"authors\": \"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\", \"year\": \"2024\", \"venue\": \"Proceedings of ICASSP\"}, {\"key\": \"knowledge_collapse2025\", \"type\": \"misc\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"authors\": \"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"sigma2026_spectral\", \"type\": \"misc\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"authors\": \"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"synthetic_eggs2026\", \"type\": \"inproceedings\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"authors\": \"Schaffelder, Max and Gatt, Albert\", \"year\": \"2026\", \"venue\": \"Findings of ACL\"}, {\"key\": \"shi2025_closer_look\", \"type\": \"inproceedings\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"authors\": \"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\", \"year\": \"2025\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"yi2026_escaping_collapse\", \"type\": \"inproceedings\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"authors\": \"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\", \"year\": \"2026\", \"venue\": \"3rd DATA-FM Workshop at ICLR 2026\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"type\": \"inproceedings\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"authors\": \"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\", \"year\": \"2025\", \"venue\": \"Findings of EMNLP\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"type\": \"misc\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\", \"authors\": \"Bakshi, Soham and Chakraborty, Sunrit\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wang2026_contamination\", \"type\": \"misc\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\", \"authors\": \"Wang, Kevin and Niu, Hongqian and Li, Didong\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"falahati2026_curated\", \"type\": \"misc\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\", \"authors\": \"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wu2025_detection_survey\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"gehrmann2019_gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of ACL: System Demonstrations\"}, {\"key\": \"mitchell2023_detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"fast_detectgpt2024\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"binoculars2024\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"diveye2026\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research (TMLR)\"}, {\"key\": \"sadasivan2023_paraphrase\", \"type\": \"misc\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2023\", \"venue\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"type\": \"misc\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"authors\": \"Pudasaini, Shushanta and Miralles-Pech\\\\'uan, Luis and Lillis, David and Llorens ...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"type\": \"misc\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"type\": \"inproceedings\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"authors\": \"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\", \"year\": \"2025\", \"venue\": \"Findings of ACL\"}, {\"key\": \"uchendu2020_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of EMNLP\"}, {\"key\": \"editlens2026\", \"type\": \"inproceedings\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"authors\": \"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\", \"year\": \"2026\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"tulchinskii2023_intrinsic_dim\", \"type\": \"inproceedings\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"authors\": \"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\", \"year\": \"2023\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"verma2024_ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of NAACL\"}, {\"key\": \"wang2024_m4_semeval\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\"}, {\"key\": \"li2024_mage\", \"type\": \"inproceedings\", \"title\": \"MAGE: Machine-generated Text Detection in the Wild\", \"authors\": \"Li, Yongkang and Li, Donghao and Yang, Yue and Hu, Baotian and Zhang, Min\", \"year\": \"2024\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"yang2024_dnagpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"kirchenbauer2023_watermark\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"holtzman2020_nucleus\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"finlayson2024_closing\", \"type\": \"inproceedings\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"authors\": \"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"type\": \"inproceedings\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"authors\": \"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\", \"year\": \"2025\", \"venue\": \"Proceedings of COLING\"}, {\"key\": \"wiher2022_decoding\", \"type\": \"article\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"authors\": \"Wiher, Gian and Meister, Clara and Cotterell, Ryan\", \"year\": \"2022\", \"venue\": \"Transactions of the Association for Computational Linguistics\"}, {\"key\": \"basu2021_mirostat\", \"type\": \"inproceedings\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"authors\": \"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\", \"year\": \"2021\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"coral2020\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"cloc2025\", \"type\": \"inproceedings\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"authors\": \"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\", \"year\": \"2025\", \"venue\": \"Proceedings of CVPR\"}, {\"key\": \"hu2022lora\", \"type\": \"inproceedings\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"authors\": \"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\", \"year\": \"2022\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"he2021_deberta_v3\", \"type\": \"inproceedings\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"authors\": \"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\", \"year\": \"2023\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"liu2019_roberta\", \"type\": \"misc\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"authors\": \"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\", \"year\": \"2019\", \"venue\": \"\"}, {\"key\": \"dsir2023\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"qurating2024\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"penedo2024_fineweb\", \"type\": \"inproceedings\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"authors\": \"\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"type\": \"article\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"authors\": \"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\"uller, Klaus-Robert\", \"year\": \"2007\", \"venue\": \"Journal of Machine Learning Research\"}, {\"key\": \"c2pa2024\", \"type\": \"misc\", \"title\": \"C2PA Specification: Coalition for Content Provenance and Authenticity\", \"authors\": \"C2PA\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"qwen2.5\", \"type\": \"misc\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"llama3\", \"type\": \"misc\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"schaeffer2025\", \"type\": \"misc\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"authors\": \"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"frank2001\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of ECML\"}, {\"key\": \"rennie2005\", \"type\": \"inproceedings\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"authors\": \"Rennie, Jason D. M. and Srebro, Nathan\", \"year\": \"2005\", \"venue\": \"Proceedings of IJCAI Workshop on Advances in Preference Handling\"}, {\"key\": \"mccullagh1980_ordinal\", \"type\": \"article\", \"title\": \"Regression Models for Ordinal Data\", \"authors\": \"McCullagh, Peter\", \"year\": \"1980\", \"venue\": \"Journal of the Royal Statistical Society: Series B\"}, {\"key\": \"wenzek2020_ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of LREC\"}, {\"key\": \"dugan2024_raid\", \"type\": \"inproceedings\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"authors\": \"Dugan, Liam and Hwang, Alyssa and Trhl\\\\'\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\", \"year\": \"2024\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"guo2024curious\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of NAACL\"}, {\"key\": \"padmakumar2024diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"briesch2024selfconsuming\", \"type\": \"misc\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"authors\": \"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"seddik2024synthetic\", \"type\": \"misc\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"authors\": \"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"janitza2016_ordinal_rf\", \"type\": \"article\", \"title\": \"Random Forest for Ordinal Responses: Prediction and Variable Selection\", \"authors\": \"Janitza, Silke and Tutz, Gerhard and Boulesteix, Anne-Laure\", \"year\": \"2016\", \"venue\": \"Computational Statistics \\\\& Data Analysis\"}, {\"key\": \"shi2024_minkprob\", \"type\": \"inproceedings\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"authors\": \"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"christ2024_undetectable\", \"type\": \"inproceedings\", \"title\": \"Undetectable Watermarks for Language Models\", \"authors\": \"Christ, Miranda and Gunn, Sam and Zamir, Or\", \"year\": \"2024\", \"venue\": \"Proceedings of COLT\"}, {\"key\": \"bertrand2024_stability\", \"type\": \"inproceedings\", \"title\": \"On the Stability of Iterative Retraining of Generative Models on their own Data\", \"authors\": \"Bertrand, Quentin and Bose, Avishek Joey and Duplessis, Alexandre and Jiralerspo...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"guo2024_biscope\", \"type\": \"inproceedings\", \"title\": \"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\", \"authors\": \"Guo, Hanxi and Cheng, Siyuan and Jin, Xiaolong and Zhang, Zhuo and Zhang, Kaiyua...\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"kasa2024_ordinality\", \"type\": \"inproceedings\", \"title\": \"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\", \"authors\": \"Kasa, Siva Rajesh and Goel, Aniket and Gupta, Karan and Roychowdhury, Sumegh and...\", \"year\": \"2024\", \"venue\": \"Findings of ACL\"}], \"tex_citations\": [{\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"citet\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"seddik2024synthetic\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"bertrand2024_stability\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"citet\"}, {\"key\": \"shi2025_closer_look\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"citet\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"citet\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"yi2026_escaping_collapse\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"wenzek2020_ccnet\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"marchi2024_heat_death\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"wang2026_contamination\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"knowledge_collapse2025\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_demystified\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"guo2024curious\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"briesch2024selfconsuming\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"padmakumar2024diversity\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"sigma2026_spectral\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"synthetic_eggs2026\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"schaeffer2025\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"wu2025_detection_survey\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"guo2024_biscope\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"gehrmann2019_gltr\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"verma2024_ghostbuster\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"yang2024_dnagpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"tulchinskii2023_intrinsic_dim\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pu2026_generator_barrier\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"wang2024_m4_semeval\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"dugan2024_raid\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"li2024_mage\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"citet\"}, {\"key\": \"shi2024_minkprob\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"christ2024_undetectable\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"editlens2026\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"mohamed2025_broken_telephone\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"coral2020\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"kasa2024_ordinality\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"citet\"}, {\"key\": \"janitza2016_ordinal_rf\", \"file\": \"related_work.tex\", \"line\": 26, \"command\": \"citet\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"finlayson2024_closing\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"wiher2022_decoding\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"basu2021_mirostat\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"cite\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"method.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"hu2022lora\", \"file\": \"method.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"theory.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"theory.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"bertrand2024_stability\", \"file\": \"theory.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 56, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 126, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shi2024_minkprob\", \"file\": \"generalization.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"generalization.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"generalization.tex\", \"line\": 114, \"command\": \"cite\"}, {\"key\": \"qwen2.5\", \"file\": \"generalization.tex\", \"line\": 114, \"command\": \"cite\"}, {\"key\": \"penedo2024_fineweb\", \"file\": \"conclusion.tex\", \"line\": 26, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"conclusion.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"conclusion.tex\", \"line\": 35, \"command\": \"citet\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"conclusion.tex\", \"line\": 57, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"conclusion.tex\", \"line\": 57, \"command\": \"cite\"}, {\"key\": \"he2021_deberta_v3\", \"file\": \"section_appendix.tex\", \"line\": 207, \"command\": \"cite\"}, {\"key\": \"liu2019_roberta\", \"file\": \"section_appendix.tex\", \"line\": 207, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"section_appendix.tex\", \"line\": 234, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"section_appendix.tex\", \"line\": 590, \"command\": \"cite\"}, {\"key\": \"mccullagh1980_ordinal\", \"file\": \"section_appendix.tex\", \"line\": 591, \"command\": \"cite\"}, {\"key\": \"frank2001\", \"file\": \"section_appendix.tex\", \"line\": 591, \"command\": \"cite\"}, {\"key\": \"rennie2005\", \"file\": \"section_appendix.tex\", \"line\": 591, \"command\": \"citet\"}, {\"key\": \"binoculars2024\", \"file\": \"section_appendix.tex\", \"line\": 713, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"section_appendix.tex\", \"line\": 713, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"section_appendix.tex\", \"line\": 719, \"command\": \"cite\"}, {\"key\": \"shi2024_minkprob\", \"file\": \"section_appendix.tex\", \"line\": 720, \"command\": \"cite\"}, {\"key\": \"dsir2023\", \"file\": \"section_appendix.tex\", \"line\": 776, \"command\": \"cite\"}, {\"key\": \"qurating2024\", \"file\": \"section_appendix.tex\", \"line\": 776, \"command\": \"cite\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"file\": \"section_appendix.tex\", \"line\": 779, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"section_appendix.tex\", \"line\": 783, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"section_appendix.tex\", \"line\": 784, \"command\": \"cite\"}, {\"key\": \"hu2022lora\", \"file\": \"section_appendix.tex\", \"line\": 800, \"command\": \"citet\"}], \"online_verification\": [{\"key\": \"shumailov2024_nature\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_demystified\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Model Collapse Demystified: The Case of Regression\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"alemohammad2024_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"knowledge_collapse2025\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"status\": \"not_found\", \"confidence\": 0.288, \"matched_title\": \"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.29 below threshold 0.82\"}, {\"key\": \"sigma2026_spectral\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthetic_eggs2026\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shi2025_closer_look\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yi2026_escaping_collapse\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Machine-generated text detection prevents language model collapse\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2026_contamination\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"falahati2026_curated\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\", \"status\": \"not_found\", \"confidence\": 0.0, \"matched_title\": \"\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"no results from OpenAlex\"}, {\"key\": \"wu2025_detection_survey\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gehrmann2019_gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mitchell2023_detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"fast_detectgpt2024\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars2024\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye2026\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sadasivan2023_paraphrase\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can AI-Generated Text be Reliably Detected?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu2020_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"editlens2026\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"tulchinskii2023_intrinsic_dim\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"verma2024_ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2024_m4_semeval\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"li2024_mage\", \"title\": \"MAGE: Machine-generated Text Detection in the Wild\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MAGE: Machine-generated Text Detection in the Wild\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yang2024_dnagpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"kirchenbauer2023_watermark\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"holtzman2020_nucleus\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"finlayson2024_closing\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Closing the Curious Case of Neural Text Degeneration\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=garces arias vs api=arias\"], \"note\": \"\"}, {\"key\": \"wiher2022_decoding\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On Decoding Strategies for Neural Text Generators\", \"matched_year\": \"2022\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"basu2021_mirostat\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"coral2020\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cloc2025\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"hu2022lora\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"he2021_deberta_v3\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"matched_year\": \"2021\", \"mismatch_fields\": [\"year: bib=2023 vs api=2021\"], \"note\": \"\"}, {\"key\": \"liu2019_roberta\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"status\": \"not_found\", \"confidence\": 0.495, \"matched_title\": \"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"dsir2023\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating2024\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"penedo2024_fineweb\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"matched_year\": \"2007\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"c2pa2024\", \"title\": \"C2PA Specification: Coalition for Content Provenance and Authenticity\", \"status\": \"not_found\", \"confidence\": 0.409, \"matched_title\": \"Integrating Content Authenticity with DASH Video Streaming\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.41 below threshold 0.82\"}, {\"key\": \"qwen2.5\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"status\": \"not_found\", \"confidence\": 0.333, \"matched_title\": \"Can Open Large Language Models Catch Vulnerabilities?\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.33 below threshold 0.82\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"schaeffer2025\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Position: Model Collapse Does Not Mean What You Think\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank2001\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"rennie2005\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"status\": \"not_found\", \"confidence\": 0.373, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.37 below threshold 0.82\"}, {\"key\": \"mccullagh1980_ordinal\", \"title\": \"Regression Models for Ordinal Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Regression Models for Ordinal Data\", \"matched_year\": \"1980\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wenzek2020_ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dugan2024_raid\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"guo2024curious\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"padmakumar2024diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"briesch2024selfconsuming\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"seddik2024synthetic\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"janitza2016_ordinal_rf\", \"title\": \"Random Forest for Ordinal Responses: Prediction and Variable Selection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Random forest for ordinal responses: Prediction and variable selection\", \"matched_year\": \"2015\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shi2024_minkprob\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Detecting Pretraining Data from Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"christ2024_undetectable\", \"title\": \"Undetectable Watermarks for Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Undetectable Watermarks for Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bertrand2024_stability\", \"title\": \"On the Stability of Iterative Retraining of Generative Models on their own Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On the Stability of Iterative Retraining of Generative Models on their own Data\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"guo2024_biscope\", \"title\": \"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=guo vs api=cheng\"], \"note\": \"\"}, {\"key\": \"kasa2024_ordinality\", \"title\": \"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d38d6eb0-e71d-45a1-ac9d-5621edd436fa",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "df5c4126-34f0-4231-b418-104398c7734e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-review-reviewer-1-37084335/18e2781e-e5ad-47ad-895c-aafdbd2b04f0/tool-results/toolu_015jUowEUHRVxwKP1QHqw2hZ.txt",
      "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 68, \\\"total_citations\\\": 102, \\\"unique_cited_keys\\\": 67, \\\"orphan_bib\\\": 1, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 56, \\\"online_not_found\\\": 7, \\\"online_mismatch\\\": 5}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [\\\"c2pa2024\\\"], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 1, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"authors\\\": \\\"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICASSP\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\\\", \\\"authors\\\": \\\"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"authors\\\": \\\"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"authors\\\": \\\"Schaffelder, Max and Gatt, Albert\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"authors\\\": \\\"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"authors\\\": \\\"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"3rd DATA-FM Workshop at ICLR 2026\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"authors\\\": \\\"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Findings of EMNLP\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\\\", \\\"authors\\\": \\\"Bakshi, Soham and Chakraborty, Sunrit\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\\\", \\\"authors\\\": \\\"Wang, Kevin and Niu, Hongqian and Li, Didong\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\\\", \\\"authors\\\": \\\"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of ACL: System Demonstrations\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research (TMLR)\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"authors\\\": \\\"Pudasaini, Shushanta and Miralles-Pech\\\\\\\\'uan, Luis and Lillis, David and Llorens ...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"authors\\\": \\\"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of EMNLP\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"authors\\\": \\\"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"tulchinskii2023_intrinsic_dim\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"authors\\\": \\\"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NAACL\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\\\"}, {\\\"key\\\": \\\"li2024_mage\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"MAGE: Machine-generated Text Detection in the Wild\\\", \\\"authors\\\": \\\"Li, Yongkang and Li, Donghao and Yang, Yue and Hu, Baotian and Zhang, Min\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"authors\\\": \\\"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of COLING\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"authors\\\": \\\"Wiher, Gian and Meister, Clara and Cotterell, Ryan\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Transactions of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"authors\\\": \\\"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"authors\\\": \\\"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of CVPR\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"authors\\\": \\\"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"authors\\\": \\\"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"RoBERTa: A Robustly Optimized BERT Pretraining Approach\\\", \\\"authors\\\": \\\"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"penedo2024_fineweb\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"authors\\\": \\\"\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"authors\\\": \\\"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\\\\\\\\\"uller, Klaus-Robert\\\", \\\"year\\\": \\\"2007\\\", \\\"venue\\\": \\\"Journal of Machine Learning Research\\\"}, {\\\"key\\\": \\\"c2pa2024\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"C2PA Specification: Coalition for Content Provenance and Authenticity\\\", \\\"authors\\\": \\\"C2PA\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Qwen2.5: A Party of Foundation Models\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"authors\\\": \\\"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of ECML\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\\\", \\\"authors\\\": \\\"Rennie, Jason D. M. and Srebro, Nathan\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of IJCAI Workshop on Advances in Preference Handling\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"authors\\\": \\\"McCullagh, Peter\\\", \\\"year\\\": \\\"1980\\\", \\\"venue\\\": \\\"Journal of the Royal Statistical Society: Series B\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of LREC\\\"}, {\\\"key\\\": \\\"dugan2024_raid\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"authors\\\": \\\"Dugan, Liam and Hwang, Alyssa and Trhl\\\\\\\\'\\\\\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of NAACL\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"authors\\\": \\\"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"authors\\\": \\\"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"janitza2016_ordinal_rf\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Random Forest for Ordinal Responses: Prediction and Variable Selection\\\", \\\"authors\\\": \\\"Janitza, Silke and Tutz, Gerhard and Boulesteix, Anne-Laure\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Computational Statistics \\\\\\\\& Data Analysis\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"authors\\\": \\\"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"christ2024_undetectable\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"authors\\\": \\\"Christ, Miranda and Gunn, Sam and Zamir, Or\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of COLT\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"On the Stability of Iterative Retraining of Generative Models on their own Data\\\", \\\"authors\\\": \\\"Bertrand, Quentin and Bose, Avishek Joey and Duplessis, Alexandre and Jiralerspo...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"guo2024_biscope\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\\\", \\\"authors\\\": \\\"Guo, Hanxi and Cheng, Siyuan and Jin, Xiaolong and Zhang, Zhuo and Zhang, Kaiyua...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"kasa2024_ordinality\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\\\", \\\"authors\\\": \\\"Kasa, Siva Rajesh and Goel, Aniket and Gupta, Karan and Roychowdhury, Sumegh and...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"guo2024_biscope\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"tulchinskii2023_intrinsic_dim\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dugan2024_raid\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"li2024_mage\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"christ2024_undetectable\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kasa2024_ordinality\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"janitza2016_ordinal_rf\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 33, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 104, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 104, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"theory.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"theory.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"file\\\": \\\"theory.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"atlas.tex\\\", \\\"line\\\": 56, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"atlas.tex\\\", \\\"line\\\": 126, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 114, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 114, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"penedo2024_fineweb\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 26, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 35, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 57, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 57, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 207, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 207, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 234, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 590, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 591, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 591, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 591, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 713, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 713, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 719, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 720, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 776, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 776, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 779, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 783, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 784, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 800, \\\"command\\\": \\\"citet\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"title\\\": \\\"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.288, \\\"matched_title\\\": \\\"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.29 below threshold 0.82\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"title\\\": \\\"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.0, \\\"matched_title\\\": \\\"\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"no results from OpenAlex\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"tulchinskii2023_intrinsic_dim\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"li2024_mage\\\", \\\"title\\\": \\\"MAGE: Machine-generated Text Detection in the Wild\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MAGE: Machine-generated Text Detection in the Wild\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=garces arias vs api=arias\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"matched_year\\\": \\\"2022\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [\\\"year: bib=2023 vs api=2021\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"title\\\": \\\"RoBERTa: A Robustly Optimized BERT Pretraining Approach\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.495, \\\"matched_title\\\": \\\"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"penedo2024_fineweb\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"matched_year\\\": \\\"2007\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"c2pa2024\\\", \\\"title\\\": \\\"C2PA Specification: Coalition for Content Provenance and Authenticity\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.409, \\\"matched_title\\\": \\\"Integrating Content Authenticity with DASH Video Streaming\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.41 below threshold 0.82\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"title\\\": \\\"Qwen2.5: A Party of Foundation Models\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.333, \\\"matched_title\\\": \\\"Can Open Large Language Models Catch Vulnerabilities?\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.33 below threshold 0.82\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"title\\\": \\\"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.373, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.37 below threshold 0.82\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"matched_year\\\": \\\"1980\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dugan2024_raid\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"janitza2016_ordinal_rf\\\", \\\"title\\\": \\\"Random Forest for Ordinal Responses: Prediction and Variable Selection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Random forest for ordinal responses: Prediction and variable selection\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shi2024_minkprob\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"christ2024_undetectable\\\", \\\"title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bertrand2024_stability\\\", \\\"title\\\": \\\"On the Stability of Iterative Retraining of Generative Models on their own Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"On the Stability of Iterative Retraining of Generative Models on their own Data\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"guo2024_biscope\\\", \\\"title\\\": \\\"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"BiScope: AI-generated Text Detection by Checking Memorization of Preceding Tokens\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=guo vs api=cheng\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"kasa2024_ordinality\\\", \\\"title\\\": \\\"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Exploring Ordinality in Text Classification: A Comparative Study of Explicit and Implicit Techniques\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
      "numLines": 1,
      "startLine": 1,
      "totalLines": 1
    }
  },
  "sourceToolAssistantUUID": "d38d6eb0-e71d-45a1-ac9d-5621edd436fa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 74_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**  ### Venue 信息 - **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿) - **截止日期**：2026-05-25 - **页数限制**：Long paper 8 pag…",
  "leafUuid": "df5c4126-34f0-4231-b418-104398c7734e",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Runtime record

_source line 75_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Tool result

_source line 76 · 2026-05-19T03:00:46.642Z_

<details><summary>↩ Tool result · `toolu_01VKm9Jj5UMQXiXLUct72dYb`</summary>

```text
# ARR Review Form Criteria & Scoring

Based on the ARR Reviewer Guidelines, here's what I found regarding the review form:

## Scoring Dimensions

The document explicitly mentions **three scores** (as of February 2025):

1. **Soundness** - Technical validity and methodological rigor
2. **Excitement** - Personal interest level (described as "orthogonal to soundness")
3. **Overall Assessment** - Explicit recommendation for paper outcome

**Critical note:** The guidelines do not specify the numerical scales (1-5, 1-6, etc.) for these dimensions in the provided content.

## Score Interpretation Guidance

- **Soundness scores must be justified** by review text. Low soundness without documented faults indicates incomplete analysis.
- **Excitement reflects subjective taste** and doesn't require explicit reasoning.
- **Overall Assessment** is a "composite score" balancing soundness, excitement, novelty, and potential impact.

## Additional Required Fields

The guidelines reference a "Responsible NLP checklist" but don't detail other mandatory form fields beyond the three scoring dimensions.

## Good vs. Bad Review Standards

**Poor reviews exhibit:**
- Vague criticisms without specifics
- Reliance on common heuristics (H1-H17) without evidence
- Unprofessional or sarcastic tone

**Strong reviews feature:**
- "Specific and ideally understandable to chairs" without reading the full paper
- Clear justification linking scores to textual analysis
- Professional, constructive language
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4b6b850f-b506-4049-b99c-712c7edd4f58",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "5612c047-5675-4557-8435-7808d5e7d284",
  "toolUseResult": {
    "bytes": 100603,
    "code": 200,
    "codeText": "OK",
    "result": "# ARR Review Form Criteria & Scoring\n\nBased on the ARR Reviewer Guidelines, here's what I found regarding the review form:\n\n## Scoring Dimensions\n\nThe document explicitly mentions **three scores** (as of February 2025):\n\n1. **Soundness** - Technical validity and methodological rigor\n2. **Excitement** - Personal interest level (described as \"orthogonal to soundness\")\n3. **Overall Assessment** - Explicit recommendation for paper outcome\n\n**Critical note:** The guidelines do not specify the numerical scales (1-5, 1-6, etc.) for these dimensions in the provided content.\n\n## Score Interpretation Guidance\n\n- **Soundness scores must be justified** by review text. Low soundness without documented faults indicates incomplete analysis.\n- **Excitement reflects subjective taste** and doesn't require explicit reasoning.\n- **Overall Assessment** is a \"composite score\" balancing soundness, excitement, novelty, and potential impact.\n\n## Additional Required Fields\n\nThe guidelines reference a \"Responsible NLP checklist\" but don't detail other mandatory form fields beyond the three scoring dimensions.\n\n## Good vs. Bad Review Standards\n\n**Poor reviews exhibit:**\n- Vague criticisms without specifics\n- Reliance on common heuristics (H1-H17) without evidence\n- Unprofessional or sarcastic tone\n\n**Strong reviews feature:**\n- \"Specific and ideally understandable to chairs\" without reading the full paper\n- Clear justification linking scores to textual analysis\n- Professional, constructive language",
    "durationMs": 9158,
    "url": "https://aclrollingreview.org/reviewerguidelines"
  },
  "sourceToolAssistantUUID": "4b6b850f-b506-4049-b99c-712c7edd4f58",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 77 · 2026-05-19T03:02:20.794Z_

<details><summary>Logged reasoning block</summary>

```text
I now have a thorough understanding of the paper and the ARR review criteria. Let me compile my review. Let me note the key findings:

**Reference verification summary:**
- 68 bib entries, 67 cited, 1 orphan (c2pa2024)
- 56 verified, 7 not found, 5 mismatches
- Not found: knowledge_collapse2025, falahati2026_curated, mitchell2023_detectgpt (known paper, likely OpenAlex issue), liu2019_roberta (known paper), c2pa2024 (spec, not academic paper), qwen2.5 (tech report), rennie2005 (old workshop paper)


- Mismatches in author names or publication year for alemohammad2024_mad, garces_arias2025_decoding_decoded, he2021_deberta_v3, llama3, and guo2024_biscope, though these are all legitimate references that OpenAlex just indexed slightly differently.

Now I'm organizing the review according to the ARR form, which evaluates soundness, excitement, and overall assessment on 1-5 scales.

Looking at the evaluation rubric: 5 is award-worthy, 4.5 is borderline award, 4 is conference-level, 3.5 is borderline conference, 3 is findings, 2.5 is borderline findings, and 2 warrants resubmission next cycle.

I need to focus my review on four key areas: method design, experimental design, statistical validity, and reproducibility. Let me start with the method design. The ordinal classification formalization with the depth chain is clearly presented and well-motivated, but there's a disconnect between what the formalization assumes—single-model recursive chains with LoRA fine-tuning—and the messier reality of contamination in practice, which involves multiple models and more complex interactions.

The EDD definition itself is mathematically sound, though it has a notable weakness: it requires contiguous discriminable depths, and the max formulation means even one weak pair can significantly reduce the overall EDD score. Using binary random forest classifiers for pairwise discrimination is reasonable, but relying on AUC as the metric conflates discrimination ability with calibration. The threshold of T=0.70 feels somewhat arbitrary—while the paper does show sensitivity across multiple thresholds, the justification for choosing 0.70 as the primary cutoff is thin beyond the observation that 8 out of 9 cells meet that threshold.

The nineteen statistical features are intuitive and grounded in model collapse theory, though I should examine how well they actually capture the phenomena they're meant to measure. The claim that RF respects ordinal structure because 98.2% of errors fall on adjacent depths is a bit misleading—this could just mean adjacent classes are naturally harder to distinguish rather than the model actively respecting ordinality. CORAL, which explicitly handles ordinal relationships, performs within 0.6pp, so the difference isn't substantial.

For the benchmark itself, the 3×3 grid with 180K samples is well-structured across model families, decoding strategies, and depths, though restricting to 1-1.5B models limits how far these findings generalize. The BOS-seeded generation without prompts might amplify the depth signal, though the prompted validation shows only a modest -13.8pp drop on one of the nine conditions. The 5-fold stratified cross-validation is standard practice, and they've confirmed there's no per-passage lineage across depths, which rules out a major leakage concern.

The transparency here is notable—they report an earlier bug where a global counter conflated seed-group with depth, and they've documented the fix. The domain bias analysis through LOGO evaluation and seed-group controls is thorough. However, the cross-model and cross-strategy generalization reveals real limitations: leave-one-out performance drops to 66.4% overall and just 55.4% on d1-d3, while cross-strategy evaluation shows 59.1% with a boundary inversion between d1 and d2. The cross-scale experiments are limited to only a handful of 7-14B models.

On the statistical side, they provide bootstrap confidence intervals with 1,000 samples and report effect sizes and p-values from bootstrap testing. But there's a major concern lurking here: d0 inflation. The headline accuracy is heavily driven by near-perfect recall on d0, which inflates the overall performance numbers. accuracy (69-86%) is heavily inflated by near-perfect d0 classification. The more meaningful d1-d3 balanced accuracy ranges from 58.9% to 81.5% in-distribution, and drops to 55.4% cross-model and 45.9% cross-strategy. The paper reports both but the abstract leads with the inflated numbers.

**Multiple comparisons:**
- The curation PoC (Appendix H) explicitly notes "the significant RF-vs-random contrasts (p < 0.02) involve multiple pairwise comparisons that were not corrected for multiplicity." This is honest but is still a weakness.
- The feature importance analysis computes rankings across 9 cells without formal multiple comparison correction, though Kendall's W is used for concordance.
- The many p-values reported for cross-seed, cross-model, etc. are not corrected.

**Sample size issues:**
The cross-scale experiments use only 500 samples per depth compared to 5,000 at the 1-1.5B scale, resulting in wider confidence intervals that the authors acknowledge. The curation PoC relies on just 5 seeds with a non-significant primary comparison (p>0.4) despite reporting effect sizes, and the downstream probe uses 500 samples per condition with a single seed, which the authors explicitly flag as insufficient.

**Reproducibility:**
All hyperparameters are fully specified—LoRA with r=16, α=32, dropout 0.05, learning rate 2e-4, batch size 16 over 3 epochs; Random Forest with 200 trees using Gini criterion; and EDD binary RF with 500 trees. The computational requirements are documented at 200 GPU-hours on RTX PRO 6000 with PyTorch 2.10.0 and other software versions listed. Code and data will be released upon acceptance, which is standard for submission but not currently verifiable. However, critical details remain unclear: the exact Pythia-1.4B checkpoint used, how the Wikipedia subset was selected and filtered, and specific sampling parameters like repetition penalty beyond temperature and nucleus p.

Now I'm moving into the overall assessment, starting with the paper's main strengths: the novel problem formalization treating recursive depth as ordinal classification, the systematic 3×3 experimental grid with extensive generalization testing, and the honest reporting of limitations including d0 inflation and cross-strategy failures.

The comparison against strong baselines—binary detectors, membership inference, and zero-shot LLMs—is convincing, and the theoretical connection to model collapse literature provides solid grounding. The EDD metric itself is a useful contribution, and the exhaustive appendix with ablations addresses many potential reviewer concerns.

But there are significant weaknesses to address. The ecological validity gap is substantial: LoRA fine-tuning on Wikipedia at 1-1.5B scale doesn't reflect real-world contamination scenarios, and while the Limitations section acknowledges this, it doesn't actually resolve the concern. The cross-strategy transfer failure is even more problematic—achieving only 45.9% accuracy on d1-d3 with boundary inversions means the detector fails when decoding strategy is unknown, which is typically the case in deployment. Finally, the headline accuracy numbers of 69-86% are misleading because they're heavily inflated by near-perfect d0 classification.

The cross-scale results at 7-14B are underpowered with only 2-3 models and multiple confounding factors, so the "scale-dependent attenuation" claim needs more support. The downstream curation proof-of-concept is inconclusive with p>0.4 on the primary comparison, which weakens the practical motivation. I should also note that the feature importance analysis relies on data with extreme multicollinearity, so those findings warrant cautious interpretation.

Overall, this is a well-executed empirical study that identifies an important problem with careful methodology and honest reporting, but the practical utility is constrained by the transfer failure and ecological validity gap—the contributions are primarily empirical and problem-definition rather than algorithmic.

I'm leaning toward a borderline Findings paper. The problem formalization and systematic investigation are valuable contributions, but the practical limitations are substantial and the core finding—that depth signals exist but are strategy-dependent and scale-attenuated—aligns with what the model collapse literature would predict, so it's not particularly surprising.

Let me reconsider the scoring more carefully though. The paper has genuine strengths I should weigh properly against the limitations.

On the positive side, it identifies a meaningful gap between theory and practice, uses rigorous experimental methodology with proper statistical controls and seed replication, comprehensively compares baselines to isolate the value of distributional features, and the authors are transparent about limitations. The writing is clear despite the density of content.

But there are real concerns: the LoRA fine-tuning setup creates an artificial recursive scenario that doesn't reflect how model collapse actually happens in practice with full fine-tuning or pretraining from scratch. The cross-strategy failures make this impractical for deployment, the performance degradation at 14B parameters suggests it won't scale to frontier models, and the curation proof-of-concept doesn't show significant results. Plus, this is fundamentally an empirical analysis rather than a novel algorithmic contribution.

I think 3.0 to 3.5 is the right range. It's well-executed work but there's a meaningful gap between demonstrating that depth signals can detect model collapse and actually having a deployable solution.

Now I'll draft the full review. I should also verify the LaTeX formatting—the ACL template does use `\documentclass[11pt]{article}` with `\usepackage[review]{acl}`, so that's fine. But I need to check if the bibliography style is properly specified in the main document.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5612c047-5675-4557-8435-7808d5e7d284",
  "isSidechain": false,
  "requestId": "req_011CbBBU9FY3J8h768tRZS9t",
  "type": "assistant",
  "uuid": "8efda884-2073-45f1-b2d5-a26b378e6b79",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XpJgr2kaudn14fhuwYgr9F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 19359,
      "cache_creation_input_tokens": 697,
      "cache_read_input_tokens": 76916,
      "output_tokens": 3907,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 697,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 19359,
          "output_tokens": 3907,
          "cache_read_input_tokens": 76916,
          "cache_creation_input_tokens": 697,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 697
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

_source line 78 · 2026-05-19T03:02:23.339Z_

已通读全文并完成引用验证。引用验证结果：68 条 bib 条目，67 条被引用，1 条孤立（c2pa2024），56 条在线验证通过，7 条未找到（多为技术报告/workshop 论文，非伪造），5 条有轻微 mismatch（作者名或年份差异）。整体引用真实可靠。

现在撰写审稿意见。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8efda884-2073-45f1-b2d5-a26b378e6b79",
  "isSidechain": false,
  "requestId": "req_011CbBBU9FY3J8h768tRZS9t",
  "type": "assistant",
  "uuid": "f3a295fb-3ee6-4d9a-81c8-07726be995cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XpJgr2kaudn14fhuwYgr9F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 19359,
      "cache_creation_input_tokens": 697,
      "cache_read_input_tokens": 76916,
      "output_tokens": 3907,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 697,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 19359,
          "output_tokens": 3907,
          "cache_read_input_tokens": 76916,
          "cache_creation_input_tokens": 697,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 697
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

_source line 79 · 2026-05-19T03:02:29.934Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_019yc48DNB3UPLip9Z7ACh63`</summary>

```json
{
  "todos": [
    {
      "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
      "status": "completed",
      "activeForm": "搜索 ACL ARR reviewer guidelines"
    },
    {
      "content": "通读论文全文（所有章节）",
      "status": "completed",
      "activeForm": "通读论文全文"
    },
    {
      "content": "验证引用完整性和真实性",
      "status": "completed",
      "activeForm": "验证引用完整性和真实性"
    },
    {
      "content": "撰写审稿意见并汇报 Director",
      "status": "in_progress",
      "activeForm": "撰写审稿意见并汇报 Director"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f3a295fb-3ee6-4d9a-81c8-07726be995cf",
  "isSidechain": false,
  "requestId": "req_011CbBBU9FY3J8h768tRZS9t",
  "type": "assistant",
  "uuid": "b29280ec-c441-40e3-9ffa-f9165bf5bcf7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XpJgr2kaudn14fhuwYgr9F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 19359,
      "cache_creation_input_tokens": 697,
      "cache_read_input_tokens": 76916,
      "output_tokens": 3907,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 697,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 19359,
          "output_tokens": 3907,
          "cache_read_input_tokens": 76916,
          "cache_creation_input_tokens": 697,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 697
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

_source line 80 · 2026-05-19T03:02:29.940Z_

<details><summary>↩ Tool result · `toolu_019yc48DNB3UPLip9Z7ACh63`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b29280ec-c441-40e3-9ffa-f9165bf5bcf7",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "0a9c6ce1-78bd-4d44-adfc-c2c025895b56",
  "toolUseResult": {
    "oldTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "completed",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "completed",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "in_progress",
        "activeForm": "验证引用完整性和真实性"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "pending",
        "activeForm": "撰写审稿意见"
      }
    ],
    "newTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "completed",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "completed",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "completed",
        "activeForm": "验证引用完整性和真实性"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "in_progress",
        "activeForm": "撰写审稿意见并汇报 Director"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "b29280ec-c441-40e3-9ffa-f9165bf5bcf7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 81_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 1  **你的审查侧重：方法严谨性 + 实验设计 + 统计有效性 + 可复现性**  ### Venue 信息 - **目标会议**：EMNLP 2026 Main Conference (通过 ARR 统一审稿) - **截止日期**：2026-05-25 - **页数限制**：Long paper 8 pag…",
  "leafUuid": "0a9c6ce1-78bd-4d44-adfc-c2c025895b56",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Runtime record

_source line 82_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Tool call

_source line 83 · 2026-05-19T03:05:12.505Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01BnCnDmBjfRXVbM5yc2rxGw`</summary>

```json
{
  "text": "## Reviewer 1 — Round 1 审稿意见\n\n**论文**: \"How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\"\n**Venue**: EMNLP 2026 (ARR May cycle)\n**审查侧重**: 方法严谨性 + 实验设计 + 统计有效性 + 可复现性\n\n---\n\n## Summary (2-3 句)\n\n本文提出将递归生成深度估计形式化为序数分类问题，构建了一个 180K 样本的基准（3 模型族×3 解码策略×4 深度），用 Random Forest 在 19 个统计特征上实现了 69-86% 的 4 类准确率。论文定义了 Effective Discriminable Depth (EDD) 度量，并在跨模型、跨策略、跨尺度等 8 个泛化维度上进行了系统评估。这是一项扎实的实证研究和问题形式化工作，透明地报告了大量局限性，但生态效度和实际部署可行性存在显著差距。\n\n---\n\n## Strengths (逐条)\n\n**S1. 新颖且有价值的问题定义。** 递归生成深度估计是一个未被研究过的问题，填补了模型坍塌理论（假设深度已知）和二分类检测（忽略深度信息）之间的空白。将其形式化为序数分类是自然且恰当的。Introduction §1 清楚地定位了这一空白。\n\n**S2. 系统的实验设计。** 3×3 网格（模型族×解码策略）在每个 cell 内有 5,000 样本/depth，总计 180K 样本。在多个泛化轴上的评估（跨模型 LOO、跨策略 LOO、跨尺度、prompted generation、跨域 arXiv、cross-model chains）是全面的。基线覆盖了四类方法（二分类检测器、成员推理、zero-shot LLM、序数回归），且对比公平。\n\n**S3. 统计实践透明。** Bootstrap 95% CI (B=1000) 贯穿主要结果（Table 1）；domain bias 分析的三个子实验（标准 CV、LOGO、负控制）设计严谨，且作者透明报告了初始 bug（全局计数器导致 seed-group 与 depth 混淆）及修复后的结果（Appendix §G）。这种透明度值得肯定。\n\n**S4. 诚实的局限性讨论。** d0 膨胀效应、cross-strategy 失败（d1/d2 boundary inversion）、cross-scale 实验的 5 个混杂因素、单 LoRA 种子的 1-3pp 不确定性——这些都在 Limitations 中明确讨论。这种诚实远超许多同类论文。\n\n**S5. 理论-实证对应关系。** §3.1 将 tail erosion 理论预测（p90_ppl 为深度标记物）与 9/9 cells 的实验结果对照验证；strategy-dependent convergence 的理论预测（temperature d1 ≈ nucleus d2）在 GPT-2 XL 数据中得到精确确认（92.2 vs 92.3, §3.3）。\n\n**S6. 特征重要性的三重验证。** Gini、SHAP、permutation importance 三种方法的一致性（Kendall's W=0.90, p<0.005; Appendix §B）增强了 p90_ppl 和 var_surprisal 作为核心深度标记物的可信度。\n\n---\n\n## Weaknesses (逐条)\n\n**W1 [Must-Fix]. 生态效度差距过大，需更清晰的 scope 声明。**\n- 具体位置：§2.2, Limitations \"Controlled vs. ecological setting\"\n- 问题：基准使用 Wikipedia 种子文本 + 可控 LoRA 微调（1-1.5B 模型），每深度独立训练新 adapter。真实世界的递归污染涉及全量微调或预训练、混合语料（不同深度文本混合）、未知比例的合成数据。论文的 pipeline（每步完全替换训练数据）是 model collapse 理论文献的标准 setup，但与实际发生的渐进污染（accumulation setting, cf. Gerstgrasser et al. 2024）存在结构性差异。\n- 为什么影响接收：审稿人和读者需要清楚理解该方法在什么条件下 works，当前 \"recursive generation depth estimation\" 的 framing 暗示了比实际验证范围更广的适用性。\n- 建议修改方向：(1) 在 Abstract 或 Introduction 中明确声明 \"full-replacement recursive chain\" 的 scope 限制；(2) 讨论 accumulation setting（混合真实+合成数据训练）下深度信号是否存在的理论预期；(3) 即使不做实验，也应在 Discussion 中正式讨论这一 gap 与实际部署的关系。\n\n**W2 [Must-Fix]. Cross-strategy 失败是实际部署的根本障碍，但论文 framing 不够突出。**\n- 具体位置：§5.3, Table 4\n- 问题：Cross-strategy transfer 的 d1-d3 balanced accuracy 仅 45.9%（chance=33%），且出现 d1/d2 boundary inversion（d1v2 AUC < 0.5）。在实际部署中，解码策略几乎总是未知的。Two-stage pipeline 恢复 11.5pp 但仍有大幅差距。这意味着在现实条件下（未知策略），深度估计的可靠性大幅下降。\n- 为什么影响接收：论文标题和 Abstract 以 \"estimating recursive generation depth\" 为核心 claim，但该 claim 在最常见的部署场景（未知策略）下实质上不成立——d1-d3 区分仅略高于 chance。\n- 建议修改方向：(1) 在 Abstract 中更明确地 qualify 结果——当前 Abstract 第 6 行的 \"cross-model transfer reaches 66.4% (2.7× chance)\" 是有 d0 膨胀的数字，应补充 d1-d3 的 45.9%；(2) 在 Contributions 列表中增加 \"identifying cross-strategy transfer as a fundamental bottleneck\" 作为独立贡献点，而非仅作为 limitation 处理。\n\n**W3 [Should-Fix]. d0 膨胀显著，Abstract 中的数字呈现具有误导性。**\n- 具体位置：Abstract, Table 2, Table 3\n- 问题：d0 recall > 97% 在所有 9 cells 中成立。4-class accuracy (69-86%) 包含了 d0 的近完美贡献。Abstract 第 4 行 \"69-86% four-class accuracy\" 是 headline，括号内的 \"d1-d3 balanced accuracy: 71.6% within-distribution, 55.4% cross-model\" 虽然提供了修正数字但被淹没在信息过载的长句中。Cross-model 的 66.4% 被 d0 从 55.4% 抬升了 11pp。\n- 建议：在所有 headline 数字旁系统性地并列报告 d1-d3 balanced accuracy，并在 Abstract 中将 d1-d3 数字提升到与 4-class accuracy 同等的显著位置。\n\n**W4 [Should-Fix]. Cross-scale 实验证据不足以支撑 \"scale-dependent attenuation\" 的结论。**\n- 具体位置：§5.4, Table (cross_scale), Appendix §K\n- 问题：仅有 2 个 7-8B 模型（Llama-3.1-8B, Qwen2.5-7B）和 1 个 14B 模型（Qwen2.5-14B）。这 3 个数据点存在 5 个明确列出的混杂因素（QLoRA 量化、样本量缩减至 500、仅 nucleus、vocabulary mismatch、14B 自参考模型）。更关键的是，两个 7-8B 模型的 AUC 轨迹完全不同（Llama 单调递减 vs Qwen U-shaped），无法确定哪种 pattern 是主流。\n- 建议：(1) 将 \"Preliminary Cross-Scale Observations\" 的 \"Preliminary\" 保留但在 Abstract/Contributions 中降调 cross-scale 的 claim 力度；(2) 明确声明 \"cross-scale results are confounded and should be interpreted as existence proofs rather than quantitative trends.\"\n\n**W5 [Should-Fix]. Curation PoC 的 primary comparison 不显著，削弱了实用动机。**\n- 具体位置：Appendix §H, Table 8\n- 问题：RF-filtered vs unfiltered 的比较 p=0.407，effect size d_z=0.41（small），完全不显著。显著的 RF vs random comparison（p<0.02）涉及多重比较且未校正（论文自己承认）。Downstream fine-tuning probe（Appendix §L）同样在 5 seeds、500 samples 下未达显著性。\n- 为什么影响评分：论文在 Extended Discussion（Appendix §P, \"Depth-graduated curation\"）中以此作为实用场景的证据，但统计证据不支持。\n- 建议：(1) 明确将 curation PoC 标记为 \"inconclusive\"，不在 Discussion 中以 \"feasible\" 描述 depth-graduated filtering；(2) 对 RF vs random 的 3 个 comparisons 应用 Bonferroni 或 Holm 校正并报告校正后 p 值。\n\n**W6 [Should-Fix]. 多重共线性下的特征重要性解读需更多 caveat。**\n- 具体位置：§4.2, Table 2\n- 问题：19 个特征中 14-16 个 VIF>10（§2.3），有效独立维度仅 ~4-5。在严重多重共线性下，Gini importance 不可靠（会在相关特征间分散重要性）。论文在 footnote 5 中提到了这一点（\"Individual feature rankings should be interpreted cautiously\"），但正文继续以单特征 rank 作为核心叙事（\"p90_ppl ranks top-2 in all 9 cells\"）。\n- 建议：(1) 主表格应以 feature group（perplexity tail, surprisal, lexical, repetition）而非 individual feature 为分析单位；(2) 考虑使用 grouped permutation importance 或 conditional permutation importance 作为多重共线性下的补充验证。\n\n**W7 [Minor]. EDD 定义中的 AUC threshold T=0.70 选择缺乏独立的理论/实证依据。**\n- 具体位置：Definition 1 (§2.4), §4.4\n- 问题：T=0.70 被选为 \"primary threshold\" 的唯一理由是 \"8/9 cells achieve EDD≥3\"（§2.4 最后一行）。这是循环论证：选择让结果看起来最好的 threshold。虽然敏感性分析（T ∈ {0.65, 0.70, 0.75, 0.80}）有助于缓解，但仍缺乏独立的 calibration。\n- 建议：讨论 T=0.70 在 AUC 文献中的含义（对应什么水平的实际分类性能），或通过 downstream task 的需求反向确定 threshold。\n\n**W8 [Minor]. RF 的 ordinal structure 利用 claim 缺乏严格支撑。**\n- 具体位置：§2.4\n- 问题：\"RF implicitly respects ordinal structure: 98.2% of errors fall on adjacent depths (|Δ|≤1), QWK=0.89\" (Table 1 caption)。但 adjacent-class error 集中可能仅仅反映 adjacent classes 更难区分（feature overlap），而非 RF \"respects\" ordinal structure。论文引用 Janitza et al. (2016) 说 RF \"implicitly respects ordinal structure when inter-class distances are monotonic\"，这一条件在论文中通过 §4.3 的 monotonicity 结果得到部分验证，但论文的表述过于强烈。\n- 建议：弱化表述为 \"RF produces ordinally consistent predictions, with 98.2% of errors at adjacent depths\"，避免暗示 RF 有内在的序数归纳偏置。\n\n**W9 [Minor]. Reference model 与 generator 的重叠未被充分控制。**\n- 具体位置：§2.2 最后一段, Limitations \"Reference model dependency\"\n- 问题：Pythia-1.4B 同时作为三个 generator 之一和唯一的 reference model。论文认为\"Pythia 78.7% vs GPT-2 XL 85.9%\" 说明自参考无系统优势，但这忽略了一种可能性：自参考可能在某些深度边界上具有优势而在其他边界上具有劣势，宏观指标上相互抵消。Appendix §J 的 reference ablation 仅在 Pythia 生成数据上测试（not GPT-2 XL or OLMo），无法排除这一假设。\n- 建议：在至少一个非 Pythia cell（e.g., GPT-2 XL nucleus）上补充 reference model ablation，以排除 generator-reference 交互效应。\n\n---\n\n## Questions (需要作者回答)\n\n**Q1.** 在 accumulation setting（每步保留部分真实数据 + 新生成的合成数据混合训练）下，你们预期深度信号会如何变化？是否有理论上的预期或初步实验？\n\n**Q2.** Cross-model chain 实验（Appendix §K, 84.75%）中，architecture identity 与 depth 完全共变（d1=Pythia, d2=OLMo, d3=GPT-2 XL）。虽然 reverse-chain control 提供了部分证据，但能否通过 same-model-at-all-depths 的结果（即主实验）对减去 architecture signal 做定量分析？例如，比较 cross-model chain 的 per-depth confusion 与 single-model chain 的 confusion 差异。\n\n**Q3.** Table 1 的 d2 recall 系统性最低（44-73%），论文解释为 \"d2 位于深度梯度中心\"。但 d3 recall (61-80%) 一致高于 d2。为什么 d3（更远离 d0）反而比 d2 更容易分类？是否因为 d3 有更多独特的退化信号（如高 repetition）？\n\n**Q4.** Feature extraction \"requires no GPU\" 且 \"2 minutes per 5,000 samples on a single CPU core\" (Appendix §Q)。但 reference model forward pass（Pythia-1.4B）是否确实在 CPU 上运行？如果是，这在大规模部署中是否可行？如果需要 GPU，请修正这一声明。\n\n**Q5.** 论文声称 \"no per-passage lineage exists across depths\" (§2.2)。能否更明确地解释：不同深度的 5,000 个样本是否有任何间接的数据依赖关系？例如，d1 数据是在 d0 上微调后生成的，d2 数据是在 d1 上微调后生成的——即使单个 passage 无对应关系，训练数据的统计特性是有传递性的，这对 CV split 的独立性假设有何影响？\n\n---\n\n## Missing References (遗漏的重要文献)\n\n1. **Shumailov et al. (2024) \"The Curse of Recursion\"** — 虽然 Nature 版本已引用，但 arXiv 预印本中有更多关于 tail erosion 的量化分析，与本文的 p90_ppl 发现直接相关。(注: 可能已覆盖，需确认 Nature 版本是否包含相同内容)\n\n2. 引用验证中 1 条孤立 bib entry (c2pa2024, C2PA Specification) 未在正文中引用——若不使用应删除。\n\n3. 引用验证中 5 条轻微 mismatch（多为第一作者名变体或年份差异）：alemohammad2024_mad, garces_arias2025_decoding_decoded, he2021_deberta_v3 (year: bib=2023 vs api=2021), llama3, guo2024_biscope。建议核实并修正。\n\n---\n\n## Overall Assessment\n\n**Overall**: 3.0 (Findings)\n**Soundness**: 3.5/5\n**Excitement**: 3.0/5\n**Confidence**: 4/5\n\n### 评分理由\n\n**Soundness (3.5)**: 问题定义清晰，实验方法论基本严谨，统计实践透明。主要扣分点：(1) cross-scale 实验的混杂因素使核心结论之一（scale-dependent attenuation）缺乏可靠支撑；(2) d0 膨胀虽被讨论但在 headline 数字呈现上仍有误导性；(3) curation PoC 不显著却作为动机之一。\n\n**Excitement (3.0)**: 问题定义新颖且 timely（递归污染是活跃研究领域），EDD 度量有概念贡献。但 (1) 核心发现（depth signal exists in tail statistics）在模型坍塌理论预测之下并不 surprising；(2) 方法（RF on hand-crafted features）缺乏算法创新；(3) cross-strategy 失败和 scale attenuation 大幅限制了实际影响力——该方法目前仅在\"已知策略 + 1-1.5B 模型\"条件下 reliably works，这一条件在实践中罕见。\n\n**一句话总结**: 一项定义新颖、执行严谨但实用性受限的实证研究——在可控条件下证明了递归深度信号的存在，但距离实际部署（未知策略、大模型）有显著差距，适合作为 Findings 论文发表。\n\n---\n\n## Detailed Comments (逐 section)\n\n### Abstract\n- 信息密度高但几乎不可能一次读懂。建议减少括号内的数字堆砌，将核心结果分为 2-3 个清晰的 claim 层级。\n- \"69-86% four-class accuracy\" 应伴随 \"d1-d3 balanced: 59-82%\" 作为等权的修正数字。\n- \"cross-model transfer reaches 66.4% (2.7× chance)\" 中的 d1-d3 数字 (55.4%) 应被提升到同等显著位置。\n\n### Introduction (§1)\n- 叙事线清晰：递归循环 → 现有工具的空白 → perplexity tail fingerprint 的发现 → 贡献总结。\n- 第 3 段 \"consistent in direction but scale-dependent in magnitude\" 是一个好的 qualifier。\n- Contribution 列表第 3 点过于冗长，应将数字细节移至正文。\n\n### Related Work (§2)\n- 覆盖全面：model collapse theory、AI text detection、membership inference、adjacent tasks、ordinal classification、decoding strategies。\n- 与 Mohamed et al. (2025, \"Broken Telephone\") 的区分清晰：\"characterize how text degrades\" vs \"classify which iteration\"。\n- 引用密度适当（67 unique cited keys）。\n\n### Method (§3)\n- Problem Definition (§2.1): 形式化清晰。建议增加一段讨论 full-replacement vs accumulation setting 的区别。\n- Benchmark (§2.2): \"BOS-seeded generation may amplify depth signal\" — 好的自我审视。但 prompted validation 仅在 1/9 cells 上做了 (GPT-2 XL nucleus)，推广性未确立。\n- Features (§2.3): 设计合理但应更突出 effective dimensionality ~4-5 的发现。\n- EDD (§2.4): 定义数学上自洽。Footnote 2 关于 non-monotonic AUC 的讨论是必要的。\n\n### Theory (§3.1)\n- \"Scale-dependent attenuation\" 的理论预测 (α closer to 1 for larger models) 是合理的。\n- Strategy-dependent convergence 的预测与 GPT-2 XL 数据精确匹配 (92.2 vs 92.3) — 但这是 cherry-picked 的单一比较，需注意不要过度泛化。\n\n### Atlas (§4)\n- §4.1: 结构清晰，交叉效应（strategy effect 9.3pp vs model effect 7.2pp）是有趣的发现。\n- §4.2: Feature importance analysis 的主要问题是 multicollinearity (W6)。\n- §4.4: AUC decay analysis 和 EDD threshold sensitivity 是论文最有价值的分析之一。d3-vs-d4 AUC 在三个模型间的 convergence (0.750-0.784) 特别有说服力。\n\n### Generalization (§5)\n- §5.1: Baseline comparison 全面且公平。RF/XGB/LightGBM convergence within 0.4pp 有力地证明了 feature-determined ceiling。\n- §5.2: Cross-model transfer 的 d2 recall (26.8-52.6%) 是最大的弱点，特别是 Pythia holdout 的 26.8%。\n- §5.3: Cross-strategy failure 是论文最重要的负面结果。Two-stage pipeline 的 11.5pp recovery 是有趣的工程方向。\n- §5.4: Cross-scale observations 标记为 \"Preliminary\" 是恰当的。\n\n### Discussion/Conclusion\n- Discussion 过于简短（单独成节只有一段），未充分讨论 open questions。\n- 建议扩展 Discussion 部分，特别是: (1) accumulation setting; (2) 与 model collapse mitigation 策略的交互; (3) 向实际部署的 roadmap。\n\n### Limitations\n- 覆盖广泛且诚实。特别值得肯定的是 domain-dependent FPR 分析（C4 上 22.4% FPR）和 adversarial robustness 的坦诚承认。\n- 建议增加：passage-level 假设（论文假设每个 passage 深度均匀）在真实 mixed-depth documents 中的限制。（实际上 Appendix §N 讨论了 mixed-depth，但 Limitations 中未提及 segment-level estimation。更新：重新检查发现 Limitations 倒数第二段确实提到了 \"Segment-level estimation in mixed-depth documents remains open\"，这一点已覆盖。）\n\n### Appendix\n- 信息量极大，覆盖了几乎所有可预见的 reviewer 问题。\n- Temperature robustness (Appendix §E) 中 \"memorization as prerequisite\" 的发现（τ=1.1 下信号消失）是一个重要的机制性洞察。\n- Domain bias analysis (Appendix §G) 是论文的一大亮点。\n\n### 格式合规\n- `\\documentclass[11pt]{article}` + `\\usepackage[review]{acl}` — 符合 ACL 2025 模板要求。\n- 匿名化：作者为 \"Anonymous\"，正文中无自引泄露。\n- bib 中 1 条孤立条目 (c2pa2024) 应清理。",
  "reviewer_id": "1",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0a9c6ce1-78bd-4d44-adfc-c2c025895b56",
  "isSidechain": false,
  "requestId": "req_011CbBBbgk4a5uX22GXmTthc",
  "type": "assistant",
  "uuid": "d6054ad1-25da-465f-af50-18ebd9cbeb04",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xmj8R9GMBXvLkhXfSn1eT",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23302,
      "cache_read_input_tokens": 77613,
      "output_tokens": 6924,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 23302,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6924,
          "cache_read_input_tokens": 77613,
          "cache_creation_input_tokens": 23302,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 23302
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

_source line 84 · 2026-05-19T03:05:17.052Z_

<details><summary>↩ Tool result · `toolu_01BnCnDmBjfRXVbM5yc2rxGw`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d6054ad1-25da-465f-af50-18ebd9cbeb04",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "7cc597cf-4002-4d93-a447-938938f71544",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "d6054ad1-25da-465f-af50-18ebd9cbeb04",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 85 · 2026-05-19T03:05:24.026Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01PqaNCLCSxeFVNB1SaibBSW`</summary>

```json
{
  "todos": [
    {
      "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
      "status": "completed",
      "activeForm": "搜索 ACL ARR reviewer guidelines"
    },
    {
      "content": "通读论文全文（所有章节）",
      "status": "completed",
      "activeForm": "通读论文全文"
    },
    {
      "content": "验证引用完整性和真实性",
      "status": "completed",
      "activeForm": "验证引用完整性和真实性"
    },
    {
      "content": "撰写审稿意见并汇报 Director",
      "status": "completed",
      "activeForm": "撰写审稿意见"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7cc597cf-4002-4d93-a447-938938f71544",
  "isSidechain": false,
  "requestId": "req_011CbBBp1CAQpKAiMzeBD7cH",
  "type": "assistant",
  "uuid": "c40c7542-df70-46b3-8eba-9d6ed4a2f14c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018jrBR6pkHoMuRW2mj1Af7H",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6997,
      "cache_read_input_tokens": 100915,
      "output_tokens": 428,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6997,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 428,
          "cache_read_input_tokens": 100915,
          "cache_creation_input_tokens": 6997,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6997
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

_source line 86 · 2026-05-19T03:05:24.029Z_

<details><summary>↩ Tool result · `toolu_01PqaNCLCSxeFVNB1SaibBSW`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c40c7542-df70-46b3-8eba-9d6ed4a2f14c",
  "isSidechain": false,
  "promptId": "b334f719-5b6e-4252-b52a-c3c45f9e0af5",
  "type": "user",
  "uuid": "9ec84a2b-9b26-40b7-8714-0d97563acb19",
  "toolUseResult": {
    "oldTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "completed",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "completed",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "completed",
        "activeForm": "验证引用完整性和真实性"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "in_progress",
        "activeForm": "撰写审稿意见并汇报 Director"
      }
    ],
    "newTodos": [
      {
        "content": "搜索 ACL ARR reviewer guidelines 和评分标准",
        "status": "completed",
        "activeForm": "搜索 ACL ARR reviewer guidelines"
      },
      {
        "content": "通读论文全文（所有章节）",
        "status": "completed",
        "activeForm": "通读论文全文"
      },
      {
        "content": "验证引用完整性和真实性",
        "status": "completed",
        "activeForm": "验证引用完整性和真实性"
      },
      {
        "content": "撰写审稿意见并汇报 Director",
        "status": "completed",
        "activeForm": "撰写审稿意见"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "c40c7542-df70-46b3-8eba-9d6ed4a2f14c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 87_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on ordinal depth estimation methodology",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

### Runtime record

_source line 88 · 2026-05-19T03:06:56.314Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-19T03:06:56.314Z",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "content": "[Round 1 审稿请求]:\n## 交叉分享 — Reviewer 2 的完整审稿意见\n\n请逐条回应以下 Reviewer 2 的审稿意见。对每一条 Weakness 和 Question，标注：\n- **[AGREE]** 同意并说明理由\n- **[REBUT]** 反驳并提供证据（cite 具体 Section/Table/Figure）\n\n特别关注与你自己意见的**共识和分歧**。\n\n---\n\n以下是 Reviewer 2 的完整审稿原文：\n\n## Reviewer 2 — Round 1 审稿意见\n\n**审查侧重：新颖性 + 完整性 + 写作质量 + Related Work 覆盖度**\n\n### Summary\n本文提出将\"递归生成深度估计\"形式化为序数分类任务，构建了 180K 样本的基准测试，使用 19 个统计特征的 RF 在 1-1.5B 模型上达到 69-86% 的四分类精度。工作在任务定义和系统性实证分析上有真正的贡献，但在算法新颖性、规模可扩展性和生态效度方面存在显著局限。\n\n### Strengths\nS1. 任务定义的原创性。\nS2. 系统性实验设计。\nS3. 透明的局限性和诚实的报告。\nS4. Feature analysis 的洞察。\nS5. Related Work 覆盖充分（67 条引用）。\n\n### Weaknesses\nW1 [Must-Fix]. 规模可扩展性是致命瓶颈。14B 的 EDD_{0.70}=0，d0-vs-d1 AUC 降至 0.643。如果方法在 14B 已基本失效，70B+ 的可行性令人严重怀疑。\n\nW2 [Must-Fix]. 生态效度差距过大。Benchmark 使用高度受控流程，真实世界涉及混合语料、未知比例、多模型、后处理等。\n\nW3 [Must-Fix]. 算法贡献不足以支撑 EMNLP Main。分类器是标准 RF，特征是标准 perplexity 统计量。RF/XGBoost/LightGBM 在 0.4pp 内收敛说明方法论贡献几乎为零。\n\nW4 [Should-Fix]. Abstract 信息过载（200 词中 20+ 数字）。\n\nW5 [Should-Fix]. Discussion 实质缺失（Section 7 仅一段约 80 词）。\n\nW6 [Should-Fix]. d0 通胀需要更突出处理。d1-d3 balanced accuracy 仅 55.4% (cross-model) 和 45.9% (cross-strategy)。\n\nW7 [Should-Fix]. Downstream utility 证据不足。Curation PoC RF vs unfiltered p>0.4 不显著。\n\nW8 [Minor]. 写作存在轻微 AI 痕迹。\n\nW9 [Minor]. Feature trajectory 图被移入 Appendix，应保留正文。\n\n### Questions\nQ1. 14B EDD=0 是否意味着 perplexity-based features 路线在规模增长下注定失效？Higher-order moments 是否暗示 feature adaptation 策略？\nQ2. Cross-model chains 高于部分 within-distribution cells，是否因为多模型 shift 更大更易检测？\nQ3. Prompted generation 只验证 1/9 cells，13.8pp 下降是否被低估？\nQ4. τ=1.1 时 depth signal 消失，是否意味着高 temperature 可规避 depth estimation？\n\n### Missing References\n1. Muennighoff et al. (2024) \"Scaling Data-Constrained Language Models\"\n2. Self-play / iterative self-improvement 文献\n3. Ilyas et al. (2022) \"Datamodels\"\n4. 孤立 bib entry: c2pa2024\n\n### Overall: 3.0 (Findings), Confidence 4/5"
}
```

---

### Runtime record

_source line 89 · 2026-05-19T03:06:56.314Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-19T03:06:56.314Z",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0"
}
```

---

## Round 2

2 recorded events

### User

_source line 90 · 2026-05-19T03:06:56.303Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9ec84a2b-9b26-40b7-8714-0d97563acb19",
  "isSidechain": false,
  "promptId": "03743d58-e422-4cd4-a7ad-da3282b8fe53",
  "type": "user",
  "isMeta": true,
  "uuid": "667efe68-a554-4147-970c-c674dd8432c9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 91 · 2026-05-19T03:06:56.303Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "667efe68-a554-4147-970c-c674dd8432c9",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "cd901551-aac3-4839-93bc-f29c11f7ccfc",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "id": "1e0e67f2-1b54-4ab8-b5ba-f75cbed393bc",
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

5 recorded events

### User

_source line 92 · 2026-05-19T03:06:56.395Z_

[Round 1 审稿请求]:
## 交叉分享 — Reviewer 2 的完整审稿意见

请逐条回应以下 Reviewer 2 的审稿意见。对每一条 Weakness 和 Question，标注：
- **[AGREE]** 同意并说明理由
- **[REBUT]** 反驳并提供证据（cite 具体 Section/Table/Figure）

特别关注与你自己意见的**共识和分歧**。

---

以下是 Reviewer 2 的完整审稿原文：

## Reviewer 2 — Round 1 审稿意见

**审查侧重：新颖性 + 完整性 + 写作质量 + Related Work 覆盖度**

### Summary
本文提出将"递归生成深度估计"形式化为序数分类任务，构建了 180K 样本的基准测试，使用 19 个统计特征的 RF 在 1-1.5B 模型上达到 69-86% 的四分类精度。工作在任务定义和系统性实证分析上有真正的贡献，但在算法新颖性、规模可扩展性和生态效度方面存在显著局限。

### Strengths
S1. 任务定义的原创性。
S2. 系统性实验设计。
S3. 透明的局限性和诚实的报告。
S4. Feature analysis 的洞察。
S5. Related Work 覆盖充分（67 条引用）。

### Weaknesses
W1 [Must-Fix]. 规模可扩展性是致命瓶颈。14B 的 EDD_{0.70}=0，d0-vs-d1 AUC 降至 0.643。如果方法在 14B 已基本失效，70B+ 的可行性令人严重怀疑。

W2 [Must-Fix]. 生态效度差距过大。Benchmark 使用高度受控流程，真实世界涉及混合语料、未知比例、多模型、后处理等。

W3 [Must-Fix]. 算法贡献不足以支撑 EMNLP Main。分类器是标准 RF，特征是标准 perplexity 统计量。RF/XGBoost/LightGBM 在 0.4pp 内收敛说明方法论贡献几乎为零。

W4 [Should-Fix]. Abstract 信息过载（200 词中 20+ 数字）。

W5 [Should-Fix]. Discussion 实质缺失（Section 7 仅一段约 80 词）。

W6 [Should-Fix]. d0 通胀需要更突出处理。d1-d3 balanced accuracy 仅 55.4% (cross-model) 和 45.9% (cross-strategy)。

W7 [Should-Fix]. Downstream utility 证据不足。Curation PoC RF vs unfiltered p>0.4 不显著。

W8 [Minor]. 写作存在轻微 AI 痕迹。

W9 [Minor]. Feature trajectory 图被移入 Appendix，应保留正文。

### Questions
Q1. 14B EDD=0 是否意味着 perplexity-based features 路线在规模增长下注定失效？Higher-order moments 是否暗示 feature adaptation 策略？
Q2. Cross-model chains 高于部分 within-distribution cells，是否因为多模型 shift 更大更易检测？
Q3. Prompted generation 只验证 1/9 cells，13.8pp 下降是否被低估？
Q4. τ=1.1 时 depth signal 消失，是否意味着高 temperature 可规避 depth estimation？

### Missing References
1. Muennighoff et al. (2024) "Scaling Data-Constrained Language Models"
2. Self-play / iterative self-improvement 文献
3. Ilyas et al. (2022) "Datamodels"
4. 孤立 bib entry: c2pa2024

### Overall: 3.0 (Findings), Confidence 4/5

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cd901551-aac3-4839-93bc-f29c11f7ccfc",
  "isSidechain": false,
  "promptId": "03743d58-e422-4cd4-a7ad-da3282b8fe53",
  "type": "user",
  "uuid": "532b1045-4b1f-4694-897c-f9b1506e2bd0",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 93 · 2026-05-19T03:07:02.708Z_

<details><summary>Logged reasoning block</summary>

```text
The Director wants me to respond to Reviewer 2's review point by point, marking each as [AGREE] or [REBUT] with evidence from the paper. Let me go through each weakness and question carefully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "532b1045-4b1f-4694-897c-f9b1506e2bd0",
  "isSidechain": false,
  "requestId": "req_011CbBBwUJ29SgKB2y5ktve7",
  "type": "assistant",
  "uuid": "e6896801-6941-45fa-966b-5122628d3f34",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013qRCmF4y2pHEW7hu95Y8Xp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1166,
      "cache_read_input_tokens": 108382,
      "output_tokens": 3857,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1166,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 3857,
          "cache_read_input_tokens": 108382,
          "cache_creation_input_tokens": 1166,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1166
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

_source line 94 · 2026-05-19T03:07:03.529Z_

逐条回应 Reviewer 2 的审稿意见。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6896801-6941-45fa-966b-5122628d3f34",
  "isSidechain": false,
  "requestId": "req_011CbBBwUJ29SgKB2y5ktve7",
  "type": "assistant",
  "uuid": "749ef52a-13e6-41c0-9a95-67e510216fd9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013qRCmF4y2pHEW7hu95Y8Xp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1166,
      "cache_read_input_tokens": 108382,
      "output_tokens": 3857,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1166,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 3857,
          "cache_read_input_tokens": 108382,
          "cache_creation_input_tokens": 1166,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1166
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

_source line 95 · 2026-05-19T03:08:22.570Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01Nw9xHdYW7vh9argRb93GEU`</summary>

```json
{
  "text": "## Reviewer 1 对 Reviewer 2 审稿意见的交叉回应\n\n---\n\n### Weaknesses 逐条回应\n\n**[AGREE] R2-W1: 规模可扩展性是致命瓶颈。**\n同意这是核心问题。14B 的 EDD_{0.70}=0（Table in §5.4 / Appendix §K）确实令人担忧。但我补充两点 nuance：\n1. 14B 的 d0v1 AUC=0.643 存在自参考混杂（Qwen2.5-14B 用自身做 reference model，与所有其他实验用 Pythia-1.4B 不同），论文在 Appendix §K Confounds 中明确列出了这一点。因此 14B 的数字不能直接与 1-1.5B 比较——信号衰减和参考模型变更的效应被混淆了。\n2. 但即便打折，d1-d3 balanced accuracy 57.4%（chance=33%）说明信号确实在衰减。R2 的推论（70B+ 可行性存疑）是合理的。\n建议作者：如果可能，用 Pythia-1.4B 作为 14B 的 reference model 补充一组实验，以分离 scale effect 和 reference model effect。\n\n**[AGREE] R2-W2: 生态效度差距过大。**\n与我的 W1 完全一致。我在自己的审稿中也将此列为 Must-Fix。论文的 full-replacement recursive chain 与真实世界的 accumulation setting 存在结构性差异。论文 Limitations 中的 \"Controlled vs. ecological setting\" 段承认了这一点，但 framing 不够突出。\n\n**[REBUT] R2-W3: 算法贡献不足以支撑 EMNLP Main。**\n部分不同意。R2 认为 \"方法论贡献几乎为零\"，但我认为这低估了以下贡献：\n1. **任务形式化本身就是贡献**——论文第 18 行明确声明 \"This paper is an empirical study and problem formalization rather than an algorithmic contribution\"（Introduction §1）。EMNLP/ACL 接收过大量以 benchmark + systematic analysis 为主的论文（如 RAID [Dugan et al. 2024, cited]、M4-SemEval [Wang et al. 2024, cited]），算法新颖性不是唯一接收标准。\n2. **EDD 度量**是一个有概念价值的新定义（Definition 1, §2.4），虽然数学上简单，但将 model collapse 的理论预测操作化为可测量的度量。\n3. **Depth Degradation Atlas** 的系统性分析揭示了非平凡的发现：strategy effect (9.3pp) > model effect (7.2pp)（§4.1）；feature hierarchy 随深度变化（shallow: var_surprisal dominates, deep: p90_ppl dominates, §4.2）；temperature d1 ≈ nucleus d2 的精确验证（§3.3）。\n4. RF/XGB/LightGBM 收敛恰恰证明了 **feature 的价值**而非方法论的无贡献——它意味着核心贡献在 feature design + task formalization，而非 classifier engineering。\n\n但我同意这更适合 Findings 而非 Main（与我的 Overall 3.0 一致），因为缺乏推动方法边界的算法创新。R2 将此定为 Must-Fix 似乎过强——这是 scope/positioning 问题而非缺陷。\n\n**[AGREE] R2-W4: Abstract 信息过载。**\n同意。Abstract 7 行中塞入了 20+ 数字和多层括号嵌套，一次阅读几乎无法消化。我在自己的 Detailed Comments 中也指出了这一点。建议作者将 Abstract 重构为 3 个清晰的 claim 层级，数字细节移至正文。\n\n**[AGREE] R2-W5: Discussion 实质缺失。**\n同意。Section 7 仅一段约 80 词，实质上是 Results 的摘要而非 Discussion。我在自己的 Detailed Comments 中也建议扩展 Discussion，特别是 (1) accumulation setting, (2) 与 model collapse mitigation 策略的交互, (3) 向实际部署的 roadmap。Appendix §P \"Extended Discussion\" 有更多内容，但核心 discussion 不应被放逐到附录。\n\n**[AGREE] R2-W6: d0 通胀需要更突出处理。**\n与我的 W3 完全一致。d1-d3 balanced accuracy 55.4% (cross-model) 和 45.9% (cross-strategy) 才是评估该方法实际能力的关键数字。Abstract 中这些数字被淹没在括号嵌套中。\n\n**[AGREE] R2-W7: Downstream utility 证据不足。**\n与我的 W5 完全一致。RF vs unfiltered p=0.407 是不显著的。RF vs random 的显著结果（p<0.02）未做多重比较校正。\n\n**[REBUT] R2-W8: 写作存在轻微 AI 痕迹。**\nR2 未给出具体例子，这一评价缺乏证据支撑。论文 Ethics Statement 最后一行坦诚声明 \"This research used AI coding assistants for experiment implementation and writing drafts. All scientific decisions, experimental design, and result interpretation were conducted by the authors.\"（Limitations/Ethics §末尾）。在当前学术环境下，使用 AI 辅助写作是常见做法，只要科学判断由作者做出。除非 R2 能指出具体的 AI 痕迹导致了理解障碍或质量下降，否则这不应作为评分依据。我自己通读全文，写作质量总体在 acceptable 范围内（信息密度过高是独立问题）。\n\n**[AGREE] R2-W9: Feature trajectory 图被移入 Appendix。**\n同意。Figure (fig_feature_trajectory, Appendix §C) 是理解 depth signal 的直觉关键图——展示了 p90_ppl、var_surprisal、rep_3gram 跨深度的单调变化轨迹。正文 §4.3 提到了 monotonicity 结果但读者看不到图，削弱了可读性。建议移回正文，可缩小尺寸。\n\n---\n\n### Questions 逐条回应\n\n**[AGREE] R2-Q1: 14B EDD=0 是否意味着 perplexity-based features 路线注定失效？**\n好问题。论文 Appendix §K 段 (3) 确实观察到 14B 的 feature importance 发生结构性转变（higher-order moments 取代 first-order tail statistics），这暗示了一种可能的 feature adaptation 路线。但论文未探索这一方向。我认为这是 future work 而非当前论文的缺陷——论文明确将 cross-scale 标记为 \"Preliminary\"（§5.4 标题）。\n\n**[REBUT] R2-Q2: Cross-model chains 高于部分 within-distribution cells，是否因为多模型 shift 更大更易检测？**\nR2 的假设有一定道理，但论文提供了反证：reverse-chain control（GPT-2 XL→OLMo→Pythia）达到 85.75%，与 forward chain（84.75%）统计不可区分（Appendix §K \"Reverse-chain control\"）。如果高准确率仅因为 \"多模型 shift 更大\"，那么 reverse chain 应该产生不同的 per-depth accuracy pattern（因为 model-depth assignment 完全反转），但两者的准确率几乎相同。更可能的解释是：跨模型链中每步的分布 shift 是**累积的**（depth signal + architecture shift 叠加），而非单纯由 architecture fingerprint 驱动。不过我同意 confound 未被完全排除——84.75% 中有多少来自 depth signal vs architecture shift 的定量分解是缺失的。\n\n**[AGREE] R2-Q3: Prompted generation 只验证 1/9 cells，13.8pp 下降是否被低估？**\n与我在 W1 中的观点一致。论文 Limitations 倒数第 2 段承认 \"Prompted generation was validated on only 1 of 9 cells (GPT-2 XL nucleus); generalization to other model-strategy configurations under prompted conditions is not established.\" 但这一 caveat 在正文 §5.3 和 Abstract 中不够突出。如果其他 cells（特别是较弱的 Pythia top-k, 68.9%）下的 prompted-generation drop 更大，实际性能可能低于 55%。\n\n**[AGREE] R2-Q4: τ=1.1 时 depth signal 消失，是否意味着高 temperature 可规避？**\n是的，这是一个有意义的 adversarial 发现。Appendix §E 的 \"memorization as prerequisite\" 分析（τ=1.1 时训练 loss 几乎不下降，2.27→1.91→1.85）提供了机制解释：高 entropy 输出抵抗 memorization，因此 depth-dependent distributional shift 不会累积。但需要注意：τ=1.1 的文本质量可能已显著下降（higher entropy = more noise），所以 \"规避 depth estimation\" 的代价是生成质量损失。论文未讨论这一 trade-off。\n\n---\n\n### Missing References 回应\n\n**[AGREE] R2-MR1: Muennighoff et al. (2024) \"Scaling Data-Constrained Language Models\"。** 相关——讨论了数据量与模型规模的 scaling，与本文的 scale-dependent attenuation 有联系。应引用。\n\n**[REBUT] R2-MR2: Self-play / iterative self-improvement 文献。** 方向相关但不直接。Self-play 中的 iteration 是 policy optimization，不是 recursive generation chain。不是必须引用但可在 Related Work \"Adjacent Tasks\" 段提及。\n\n**[AGREE] R2-MR3: Ilyas et al. (2022) \"Datamodels\"。** 与 data provenance 和 data influence 相关，可在 Extended Discussion \"Toward a provenance toolkit\" 段引用。\n\n**[AGREE] R2-MR4: 孤立 bib entry c2pa2024。** 与我的引用验证结果一致——c2pa2024 在 bib 中但未被引用，应删除或在 Discussion 中引用。\n\n---\n\n### 共识与分歧总结\n\n**核心共识（R1 与 R2 一致的问题）：**\n1. 生态效度差距（R1-W1, R2-W2）\n2. d0 膨胀的 headline 误导性（R1-W3, R2-W6）\n3. Downstream utility 不显著（R1-W5, R2-W7）\n4. Abstract 信息过载（R1-Detailed, R2-W4）\n5. Discussion 缺失（R1-Detailed, R2-W5）\n6. Prompted generation 验证不足（R1-Q implicit, R2-Q3）\n7. 孤立 bib entry c2pa2024（R1-MR, R2-MR4）\n\n**主要分歧：**\n1. **算法贡献 (R2-W3)**：R2 认为 Must-Fix，我认为这是 scope/positioning 问题而非缺陷。论文明确自我定位为 empirical study + problem formalization。Benchmark + systematic analysis 类论文在 *ACL 有先例（RAID, M4-SemEval）。更适合 Findings 但不是 reject 理由。\n2. **AI 写作痕迹 (R2-W8)**：R2 未提供具体例子，我认为在作者已坦诚声明使用 AI 辅助的情况下，这不应作为评分依据。\n3. **Scale 问题的严重程度 (R2-W1 vs R1-W4)**：R2 将此列为 Must-Fix（\"致命瓶颈\"），我列为 Should-Fix。区别在于：我认为 14B 的自参考混杂使该数据点不可靠，因此 \"scale attenuation\" 的证据本身是 weak 的（既不能证明 works 也不能证明 fails）；R2 将 14B 结果视为 face value 并推断 70B+ 必然失效。在混杂未被分离之前，两种推断都缺乏充分依据。\n\n**评分一致：** 两位 Reviewer 均给出 Overall 3.0 (Findings), Confidence 4/5。",
  "reviewer_id": "1",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "749ef52a-13e6-41c0-9a95-67e510216fd9",
  "isSidechain": false,
  "requestId": "req_011CbBBwUJ29SgKB2y5ktve7",
  "type": "assistant",
  "uuid": "6e64cea5-b227-4de7-96fb-24fb9c93cecb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013qRCmF4y2pHEW7hu95Y8Xp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1166,
      "cache_read_input_tokens": 108382,
      "output_tokens": 3857,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1166,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 3857,
          "cache_read_input_tokens": 108382,
          "cache_creation_input_tokens": 1166,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1166
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

_source line 96 · 2026-05-19T03:08:26.732Z_

<details><summary>↩ Tool result · `toolu_01Nw9xHdYW7vh9argRb93GEU`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6e64cea5-b227-4de7-96fb-24fb9c93cecb",
  "isSidechain": false,
  "promptId": "03743d58-e422-4cd4-a7ad-da3282b8fe53",
  "type": "user",
  "uuid": "9e115932-5400-48ab-9aac-9185fce1b4c3",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "6e64cea5-b227-4de7-96fb-24fb9c93cecb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_1_37084335",
  "sessionId": "18e2781e-e5ad-47ad-895c-aafdbd2b04f0",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

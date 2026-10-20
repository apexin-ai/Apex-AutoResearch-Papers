# Research conversation: [Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。 ## 论文信息 - 标题: "Depth Fingerprinting: Detecting 

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 75
- **Recorded user turns:** 1
- **Tool calls:** 19
- **Original source:** `logs/chats/exported-trajectories/account-3/066b279c-ffce-4f4d-ae71-63c4ec55d181.jsonl`
- **Structured JSON:** [`4033544137c25d14554c.json`](../../sessions/40/4033544137c25d14554c.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-20T02:53:39.746Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T02:53:39.746Z",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "content": "[Round 1 审稿请求]:\n你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。\n\n## 论文信息\n- 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\"\n- 论文路径: /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/docs/paper/main.tex\n- PDF: /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf\n\n## Venue 要求\n- EMNLP 2026 via ARR (Long Paper)\n- 正文 ≤ 8 页（不含 Limitations、Ethics、参考文献）\n- ACL 模板 + [review] 选项，double-blind 匿名\n- 附录须双栏格式\n- Responsible NLP Checklist 通过 OpenReview 表单提交\n- Overall Assessment 评分标准：5=Consider for Award (前2.5%), 4=Conference (主会议), 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1=Do not resubmit\n- Deadline: 2026-05-25 AoE\n\n## 你的审查侧重\n1. **新颖性**: DDR 概念相对于 model collapse / iterative text degradation 文献的增量贡献是否足够；与并行工作（Mohamed et al. 2025, Geng et al. 2026 等）的区分是否充分\n2. **Related Work 覆盖**: 是否遗漏重要相关工作；引用是否真实（特别注意 LLM 生成的虚假引用）；bib 是否有 orphan entries\n3. **Framing / Claims**: Abstract、Introduction、Conclusion 的声明是否被实验数据支撑；是否存在 overclaim（如泛化性声明 vs 实际条件限制）\n4. **写作质量**: 术语一致性；叙事逻辑；表格/图标 caption 是否自洽；数据引用精度\n5. **格式合规**: 页数限制；匿名合规；附录双栏格式；Limitations 章节是否存在且充分\n\n请给出完整审稿意见，包含：Summary、Strengths、Weaknesses（按 Critical/Major/Minor 分级）、Questions、Missing References、Overall Assessment（评分+置信度）。"
}
```

---

### Runtime record

_source line 2 · 2026-05-20T02:53:39.749Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T02:53:39.749Z",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

## Round 1

73 recorded events

### User

_source line 3 · 2026-05-20T02:53:39.781Z_

[Round 1 审稿请求]:
你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。

## 论文信息
- 标题: "Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains"
- 论文路径: /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/docs/paper/main.tex
- PDF: /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf

## Venue 要求
- EMNLP 2026 via ARR (Long Paper)
- 正文 ≤ 8 页（不含 Limitations、Ethics、参考文献）
- ACL 模板 + [review] 选项，double-blind 匿名
- 附录须双栏格式
- Responsible NLP Checklist 通过 OpenReview 表单提交
- Overall Assessment 评分标准：5=Consider for Award (前2.5%), 4=Conference (主会议), 3.5=Borderline Conference, 3=Findings, 2.5=Borderline Findings, 2=Resubmit next cycle, 1=Do not resubmit
- Deadline: 2026-05-25 AoE

## 你的审查侧重
1. **新颖性**: DDR 概念相对于 model collapse / iterative text degradation 文献的增量贡献是否足够；与并行工作（Mohamed et al. 2025, Geng et al. 2026 等）的区分是否充分
2. **Related Work 覆盖**: 是否遗漏重要相关工作；引用是否真实（特别注意 LLM 生成的虚假引用）；bib 是否有 orphan entries
3. **Framing / Claims**: Abstract、Introduction、Conclusion 的声明是否被实验数据支撑；是否存在 overclaim（如泛化性声明 vs 实际条件限制）
4. **写作质量**: 术语一致性；叙事逻辑；表格/图标 caption 是否自洽；数据引用精度
5. **格式合规**: 页数限制；匿名合规；附录双栏格式；Limitations 章节是否存在且充分

请给出完整审稿意见，包含：Summary、Strengths、Weaknesses（按 Critical/Major/Minor 分级）、Questions、Missing References、Overall Assessment（评分+置信度）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "0ffa9507-8ef1-4fa7-ac08-dad823465e1f",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-20T02:53:39.780Z_

```json
{
  "parentUuid": "0ffa9507-8ef1-4fa7-ac08-dad823465e1f",
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
  "uuid": "17bc6493-9c5c-4e76-8410-7304d0b7bfe8",
  "timestamp": "2026-05-20T02:53:39.780Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-20T02:53:39.780Z_

```json
{
  "parentUuid": "17bc6493-9c5c-4e76-8410-7304d0b7bfe8",
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
  "uuid": "a3c18382-d109-4952-8506-149d487cf772",
  "timestamp": "2026-05-20T02:53:39.780Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 6 · 2026-05-20T02:53:39.780Z_

```json
{
  "parentUuid": "a3c18382-d109-4952-8506-149d487cf772",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "4a267422-c766-4d4f-9ec2-6086b7e3b03d",
  "timestamp": "2026-05-20T02:53:39.780Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
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
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Assistant

_source line 8 · 2026-05-20T02:53:44.374Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to perform a full review of a paper as Reviewer 2, focusing on novelty, related work coverage, framing/writing quality, and format compliance. Let me start by:

1. Loading the review-reviewer-session-start skill as instructed
2. Searching for EMNLP 2026 / ACL ARR reviewer guidelines
3. Reading the paper PDF

Let me first load the session start skill and then read the paper PDF.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4a267422-c766-4d4f-9ec2-6086b7e3b03d",
  "isSidechain": false,
  "requestId": "req_011CbD4jX92WbxFrU1vCFx8V",
  "type": "assistant",
  "uuid": "683dde80-37e4-41a9-b330-8414e0b59066",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCkRynjzCaWHLCcFphebch",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15687,
      "cache_read_input_tokens": 11841,
      "output_tokens": 353,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15687,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 353,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 15687,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15687
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

_source line 9 · 2026-05-20T02:53:45.616Z_

我将开始审稿流程：先加载 session-start skill 检查材料状态，同时读取论文 PDF。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "683dde80-37e4-41a9-b330-8414e0b59066",
  "isSidechain": false,
  "requestId": "req_011CbD4jX92WbxFrU1vCFx8V",
  "type": "assistant",
  "uuid": "1b761c10-0706-4103-87b1-b4945398bc9c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCkRynjzCaWHLCcFphebch",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15687,
      "cache_read_input_tokens": 11841,
      "output_tokens": 353,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15687,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 353,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 15687,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15687
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

_source line 10 · 2026-05-20T02:53:46.351Z_

<details open><summary>🔧 Tool call — Read · `toolu_0161rJYRZA6gosRXJHJAVRY7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/skills/review-reviewer-session-start.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1b761c10-0706-4103-87b1-b4945398bc9c",
  "isSidechain": false,
  "requestId": "req_011CbD4jX92WbxFrU1vCFx8V",
  "type": "assistant",
  "uuid": "5e702732-7505-4eb8-88f4-9db9529666de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCkRynjzCaWHLCcFphebch",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15687,
      "cache_read_input_tokens": 11841,
      "output_tokens": 353,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15687,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 353,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 15687,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15687
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

_source line 11 · 2026-05-20T02:53:47.205Z_

<details><summary>↩ Tool result · `toolu_016tVDRFZEKCB3zR7tn3fEyB`</summary>

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
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "22a9886d-1c92-4064-8134-01259c392a0f",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "bcbdaa6c-4132-4960-8b35-31934f5963d5",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "query": "select:mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "22a9886d-1c92-4064-8134-01259c392a0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-20T02:53:46.367Z_

<details><summary>↩ Tool result · reported error · `toolu_0161rJYRZA6gosRXJHJAVRY7`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5e702732-7505-4eb8-88f4-9db9529666de",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "ed93bedb-8247-470b-a7e0-eb0117e38147",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41.",
  "sourceToolAssistantUUID": "5e702732-7505-4eb8-88f4-9db9529666de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-20T02:53:47.200Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_016tVDRFZEKCB3zR7tn3fEyB`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ed93bedb-8247-470b-a7e0-eb0117e38147",
  "isSidechain": false,
  "requestId": "req_011CbD4jX92WbxFrU1vCFx8V",
  "type": "assistant",
  "uuid": "22a9886d-1c92-4064-8134-01259c392a0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCkRynjzCaWHLCcFphebch",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15687,
      "cache_read_input_tokens": 11841,
      "output_tokens": 353,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15687,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 353,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 15687,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15687
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

_source line 14 · 2026-05-20T02:53:50.574Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the paper PDF by converting it to images, and also run the reference verification. Let me start with the PDF pages and the verify_references tool.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bcbdaa6c-4132-4960-8b35-31934f5963d5",
  "isSidechain": false,
  "requestId": "req_011CbD4k5SyfFKgbovvRXtrP",
  "type": "assistant",
  "uuid": "f9d5a51d-d625-40ff-9945-0a8e659ed84d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4p1wsvdjeiSJgsM3rpj6Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1566,
      "cache_read_input_tokens": 27528,
      "output_tokens": 327,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1566,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 327,
          "cache_read_input_tokens": 27528,
          "cache_creation_input_tokens": 1566,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1566
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

_source line 15 · 2026-05-20T02:53:50.575Z_

开始读取论文 PDF 并验证引用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f9d5a51d-d625-40ff-9945-0a8e659ed84d",
  "isSidechain": false,
  "requestId": "req_011CbD4k5SyfFKgbovvRXtrP",
  "type": "assistant",
  "uuid": "5ce6b7c2-d87f-46fa-9248-25ae04845406",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4p1wsvdjeiSJgsM3rpj6Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1566,
      "cache_read_input_tokens": 27528,
      "output_tokens": 327,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1566,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 327,
          "cache_read_input_tokens": 27528,
          "cache_creation_input_tokens": 1566,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1566
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

_source line 16 · 2026-05-20T02:53:52.024Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01DfNAQ5T4vriC1HG5i1d4gk`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf",
  "project": "gen-depth-fingerprint",
  "pages": "1-6",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5ce6b7c2-d87f-46fa-9248-25ae04845406",
  "isSidechain": false,
  "requestId": "req_011CbD4k5SyfFKgbovvRXtrP",
  "type": "assistant",
  "uuid": "97aba188-f0cb-4ed1-9383-04b3c8d4ba2c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4p1wsvdjeiSJgsM3rpj6Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1566,
      "cache_read_input_tokens": 27528,
      "output_tokens": 327,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1566,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 327,
          "cache_read_input_tokens": 27528,
          "cache_creation_input_tokens": 1566,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1566
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

_source line 17 · 2026-05-20T02:53:52.498Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__verify_references · `toolu_01UGGT4E2LpZpPzBZZMDtA8h`</summary>

```json
{
  "paper_dir": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/docs/paper",
  "project": "gen-depth-fingerprint"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "97aba188-f0cb-4ed1-9383-04b3c8d4ba2c",
  "isSidechain": false,
  "requestId": "req_011CbD4k5SyfFKgbovvRXtrP",
  "type": "assistant",
  "uuid": "ff9bb416-c645-4e5d-b0bd-104d9dcd33e3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4p1wsvdjeiSJgsM3rpj6Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1566,
      "cache_read_input_tokens": 27528,
      "output_tokens": 327,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1566,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 327,
          "cache_read_input_tokens": 27528,
          "cache_creation_input_tokens": 1566,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1566
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

_source line 18 · 2026-05-20T02:53:52.781Z_

<details><summary>↩ Tool result · `toolu_01DfNAQ5T4vriC1HG5i1d4gk`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"images\": [{\"page\": 1, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p1.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 441.3}, {\"page\": 2, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p2.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 518.1}, {\"page\": 3, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p3.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 502.8}, {\"page\": 4, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p4.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 498.2}, {\"page\": 5, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p5.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 515.1}, {\"page\": 6, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p6.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 479.7}], \"total_pages\": 31, \"rendered_pages\": 6, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "97aba188-f0cb-4ed1-9383-04b3c8d4ba2c",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "fd8358f5-ac6c-4e86-b835-e48873f2e9d5",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"images\\\": [{\\\"page\\\": 1, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p1.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 441.3}, {\\\"page\\\": 2, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p2.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 518.1}, {\\\"page\\\": 3, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p3.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 502.8}, {\\\"page\\\": 4, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p4.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 498.2}, {\\\"page\\\": 5, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p5.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 515.1}, {\\\"page\\\": 6, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p6.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 479.7}], \\\"total_pages\\\": 31, \\\"rendered_pages\\\": 6, \\\"dpi\\\": 150, \\\"output_dir\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"images\": [{\"page\": 1, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p1.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 441.3}, {\"page\": 2, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p2.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 518.1}, {\"page\": 3, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p3.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 502.8}, {\"page\": 4, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p4.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 498.2}, {\"page\": 5, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p5.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 515.1}, {\"page\": 6, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p6.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 479.7}], \"total_pages\": 31, \"rendered_pages\": 6, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "97aba188-f0cb-4ed1-9383-04b3c8d4ba2c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-20T02:54:50.867Z_

<details><summary>↩ Tool result · `toolu_01UGGT4E2LpZpPzBZZMDtA8h`</summary>

```text
&lt;persisted-output>
Output too large (58.6KB). Full output saved to: /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/066b279c-ffce-4f4d-ae71-63c4ec55d181/tool-results/toolu_01UGGT4E2LpZpPzBZZMDtA8h.txt

Preview (first 2KB):
{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 78, \"total_citations\": 85, \"unique_cited_keys\": 61, \"orphan_bib\": 17, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 64, \"online_not_found\": 9, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [\"abburi_multifaceted\", \"attractor_cycles\", \"corn_ordinal\", \"covington2010mattr\", \"defactify_dataset\", \"golchin2024time\", \"longpre2024data\", \"mccarthy2010mtld\", \"neal2017surveying\", \"oren2024proving\", \"pang_opinion_mining\", \"raid\", \"self_rewarding_lms\", \"spin\", \"taghipour_neural_essay\", \"tang2024science\", \"zhu_beat_llms\"], \"missing_bib\": [], \"orphan_count\": 17, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"mccarthy2010mtld\", \"type\": \"article\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"authors\": \"McCarthy, Philip M. and Jarvis, Scott\", \"year\": \"2010\", \"venue\": \"Behavior Research Methods\"}, {\"key\": \"covington2010mattr\", \"type\": \"article\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"authors\": \"Covington, Michael A. and McFall, Joe D.\", \"year\": \"2010\", \"venue\": \"Journal of Quantitative Linguistics\"}, {\"key\": \"oren2024proving\", \"type\": \"inproceedings\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"authors\": \"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"golchin2024time\", \"type\": \"inproceedings\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"authors\": \"Golchin, Shahriar and Surdeanu, Mihai\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"longpre20
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ff9bb416-c645-4e5d-b0bd-104d9dcd33e3",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "e263dbb8-47ab-48c7-bf87-242936589a5d",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 78, \\\"total_citations\\\": 85, \\\"unique_cited_keys\\\": 61, \\\"orphan_bib\\\": 17, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 64, \\\"online_not_found\\\": 9, \\\"online_mismatch\\\": 5}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [\\\"abburi_multifaceted\\\", \\\"attractor_cycles\\\", \\\"corn_ordinal\\\", \\\"covington2010mattr\\\", \\\"defactify_dataset\\\", \\\"golchin2024time\\\", \\\"longpre2024data\\\", \\\"mccarthy2010mtld\\\", \\\"neal2017surveying\\\", \\\"oren2024proving\\\", \\\"pang_opinion_mining\\\", \\\"raid\\\", \\\"self_rewarding_lms\\\", \\\"spin\\\", \\\"taghipour_neural_essay\\\", \\\"tang2024science\\\", \\\"zhu_beat_llms\\\"], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 17, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"authors\\\": \\\"McCarthy, Philip M. and Jarvis, Scott\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Behavior Research Methods\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"authors\\\": \\\"Covington, Michael A. and McFall, Joe D.\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Journal of Quantitative Linguistics\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"authors\\\": \\\"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"authors\\\": \\\"Golchin, Shahriar and Surdeanu, Mihai\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"authors\\\": \\\"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"type\\\": \\\"book\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"authors\\\": \\\"Cohen, Jacob\\\", \\\"year\\\": \\\"1988\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"authors\\\": \\\"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Communications of the ACM\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"authors\\\": \\\"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"ACM Computing Surveys\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"authors\\\": \\\"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.01647\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"authors\\\": \\\"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2604.13692\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"authors\\\": \\\"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\\\\\\\\\"orn\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.03969\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"authors\\\": \\\"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"authors\\\": \\\"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"authors\\\": \\\"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1908.09203\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"authors\\\": \\\"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the ACM Web Conference\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Workshop on Semantic Evaluation\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"authors\\\": \\\"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.11550\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"authors\\\": \\\"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2510.22874\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the First Conference on Language Modeling (COLM)\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"authors\\\": \\\"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2401.10020\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"authors\\\": \\\"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 41st International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"authors\\\": \\\"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Language Resources and Evaluation Conference\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"authors\\\": \\\"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"authors\\\": \\\"Aaronson, Scott and Kirchner, Hendrik\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"authors\\\": \\\"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.05503\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of the Association for Computational Linguistics: NAACL\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"authors\\\": \\\"Stamatatos, Efstathios\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"authors\\\": \\\"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"authors\\\": \\\"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of the Conference of the European Chapter of the Association for Com...\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"authors\\\": \\\"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"authors\\\": \\\"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2603.11228\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"authors\\\": \\\"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"authors\\\": \\\"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Computational Linguistics\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"authors\\\": \\\"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"authors\\\": \\\"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.09388\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"authors\\\": \\\"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2508.14190\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"authors\\\": \\\"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"authors\\\": \\\"Guti\\\\\\\\'errez, Pedro Antonio and P\\\\\\\\'erez-Ortiz, Mar\\\\\\\\'ia and S\\\\\\\\'anchez-Monedero, Ja...\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"IEEE Transactions on Knowledge and Data Engineering\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of the European Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"authors\\\": \\\"Pang, Bo and Lee, Lillian\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"authors\\\": \\\"Taghipour, Kaveh and Ng, Hwee Tou\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"authors\\\": \\\"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Pattern Analysis and Applications\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"authors\\\": \\\"Chen, Tianqi and Guestrin, Carlos\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"authors\\\": \\\"Lakens, Dani\\\\\\\\\\\\\\\"el\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Social Psychological and Personality Science\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2407.21783\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"authors\\\": \\\"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2310.06825\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"authors\\\": \\\"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\\\", \\\"year\\\": \\\"2008\\\", \\\"venue\\\": \\\"BMC Bioinformatics\\\"}, {\\\"key\\\": \\\"zhu_beat_llms\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\\\", \\\"authors\\\": \\\"Zhu, Biru and Fang, Lifan and Sui, Jiayuan and Lu, Teng\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the 2023 Conference on Empirical Methods in Natural Language Proc...\\\"}, {\\\"key\\\": \\\"dolma\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\\\", \\\"authors\\\": \\\"Soldaini, Luca and Kinney, Rodney and Bhagia, Akshita and Schwenk, Dustin and At...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"fineweb\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"authors\\\": \\\"\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems: Datasets and Benchmarks Track\\\"}, {\\\"key\\\": \\\"mapping_llm_science\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Mapping the Increasing Use of LLMs in Scientific Papers\\\", \\\"authors\\\": \\\"Liang, Weixin and Zhang, Yaohui and Wu, Zhengxuan and Lepp, Haley and Ji, Wenlon...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Language Modeling\\\"}, {\\\"key\\\": \\\"monitoring_ai_review\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\\\", \\\"authors\\\": \\\"Liang, Weixin and Izzo, Zachary and Zhang, Yaohui and Lepp, Haley and Cao, Hanch...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"self_refine\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Refine: Iterative Refinement with Self-Feedback\\\", \\\"authors\\\": \\\"Madaan, Aman and Tandon, Niket and Gupta, Prakhar and Hallinan, Skyler and Gao, ...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"raid\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"authors\\\": \\\"Dugan, Liam and Hwang, Alyssa and Trhl\\\\\\\\'\\\\\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 62nd Annual Meeting of the Association for Computational Ling...\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dolma\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fineweb\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mapping_llm_science\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"monitoring_ai_review\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_refine\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 87, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 89, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 89, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 98, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 98, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 98, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 75, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 89, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"file\\\": \\\"appendix_qlora.tex\\\", \\\"line\\\": 1, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_downstream.tex\\\", \\\"line\\\": 41, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.986, \\\"matched_title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"matched_year\\\": \\\"1989\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=cohen vs api=muller\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"matched_year\\\": \\\"2017\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.344, \\\"matched_title\\\": \\\"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.34 below threshold 0.82\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.253, \\\"matched_title\\\": \\\"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.25 below threshold 0.82\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Defending Against Neural Fake News\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.355, \\\"matched_title\\\": \\\"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.36 below threshold 0.82\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Rewarding Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.871, \\\"matched_title\\\": \\\"QLoRA: Efficient Finetuning of Quantized LLMs\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Scalable watermarking for identifying large language model outputs\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.418, \\\"matched_title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.42 below threshold 0.82\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A survey of modern authorship attribution methods\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Computational methods in authorship attribution\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.497, \\\"matched_title\\\": \\\"The TRIPOD-LLM reporting guideline for studies using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Qwen3 Technical Report\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=team vs api=yang\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.32, \\\"matched_title\\\": \\\"Large AI Models in Health Informatics: Applications, Challenges, and the Future\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.32 below threshold 0.82\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.722, \\\"matched_title\\\": \\\"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.72 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=guti\\\\\\\\'errez vs api=gutiérrez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\\\", \\\"matched_year\\\": \\\"2005\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.298, \\\"matched_title\\\": \\\"XGBoost\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.30 below threshold 0.82\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.976, \\\"matched_title\\\": \\\"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mistral 7B\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Conditional variable importance for random forests\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"zhu_beat_llms\\\", \\\"title\\\": \\\"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dolma\\\", \\\"title\\\": \\\"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fineweb\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mapping_llm_science\\\", \\\"title\\\": \\\"Mapping the Increasing Use of LLMs in Scientific Papers\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mapping the Increasing Use of LLMs in Scientific Papers\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"monitoring_ai_review\\\", \\\"title\\\": \\\"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"self_refine\\\", \\\"title\\\": \\\"Self-Refine: Iterative Refinement with Self-Feedback\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Refine: Iterative Refinement with Self-Feedback\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"raid\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 78, \"total_citations\": 85, \"unique_cited_keys\": 61, \"orphan_bib\": 17, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 64, \"online_not_found\": 9, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [\"abburi_multifaceted\", \"attractor_cycles\", \"corn_ordinal\", \"covington2010mattr\", \"defactify_dataset\", \"golchin2024time\", \"longpre2024data\", \"mccarthy2010mtld\", \"neal2017surveying\", \"oren2024proving\", \"pang_opinion_mining\", \"raid\", \"self_rewarding_lms\", \"spin\", \"taghipour_neural_essay\", \"tang2024science\", \"zhu_beat_llms\"], \"missing_bib\": [], \"orphan_count\": 17, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"mccarthy2010mtld\", \"type\": \"article\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"authors\": \"McCarthy, Philip M. and Jarvis, Scott\", \"year\": \"2010\", \"venue\": \"Behavior Research Methods\"}, {\"key\": \"covington2010mattr\", \"type\": \"article\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"authors\": \"Covington, Michael A. and McFall, Joe D.\", \"year\": \"2010\", \"venue\": \"Journal of Quantitative Linguistics\"}, {\"key\": \"oren2024proving\", \"type\": \"inproceedings\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"authors\": \"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"golchin2024time\", \"type\": \"inproceedings\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"authors\": \"Golchin, Shahriar and Surdeanu, Mihai\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"longpre2024data\", \"type\": \"inproceedings\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"authors\": \"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"cohen1988statistical\", \"type\": \"book\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"authors\": \"Cohen, Jacob\", \"year\": \"1988\", \"venue\": \"\"}, {\"key\": \"tang2024science\", \"type\": \"article\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"authors\": \"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\", \"year\": \"2024\", \"venue\": \"Communications of the ACM\"}, {\"key\": \"neal2017surveying\", \"type\": \"article\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"authors\": \"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\", \"year\": \"2017\", \"venue\": \"ACM Computing Surveys\"}, {\"key\": \"detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"dna_gpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"binoculars\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"fast_detectgpt\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"ld_score\", \"type\": \"article\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"authors\": \"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.01647\"}, {\"key\": \"intrinsic_dimension\", \"type\": \"inproceedings\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"authors\": \"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"diveye\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"generator_barrier\", \"type\": \"article\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2604.13692\"}, {\"key\": \"feat_aug_transformer\", \"type\": \"article\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"authors\": \"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\"orn\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.03969\"}, {\"key\": \"reliable_detection\", \"type\": \"article\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2025\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"paraphrase_evades\", \"type\": \"inproceedings\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"authors\": \"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"detection_possibilities\", \"type\": \"inproceedings\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"authors\": \"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"grover\", \"type\": \"inproceedings\", \"title\": \"Defending Against Neural Fake News\", \"authors\": \"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\", \"year\": \"2019\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"release_strategies\", \"type\": \"article\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"authors\": \"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1908.09203\"}, {\"key\": \"beyond_binary\", \"type\": \"inproceedings\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"authors\": \"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\", \"year\": \"2025\", \"venue\": \"Proceedings of the ACM Web Conference\"}, {\"key\": \"semeval2024_task8\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Workshop on Semantic Evaluation\"}, {\"key\": \"abburi_multifaceted\", \"type\": \"article\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"authors\": \"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.11550\"}, {\"key\": \"defactify_dataset\", \"type\": \"article\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"authors\": \"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2510.22874\"}, {\"key\": \"self_consuming_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"curse_of_recursion\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"strong_model_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"model_collapse_avoidable\", \"type\": \"inproceedings\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"Proceedings of the First Conference on Language Modeling (COLM)\"}, {\"key\": \"self_rewarding_lms\", \"type\": \"article\", \"title\": \"Self-Rewarding Language Models\", \"authors\": \"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2401.10020\"}, {\"key\": \"spin\", \"type\": \"inproceedings\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"authors\": \"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\", \"year\": \"2024\", \"venue\": \"Proceedings of the 41st International Conference on Machine Learning\"}, {\"key\": \"qlora\", \"type\": \"inproceedings\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"authors\": \"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"dsir\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"qurating\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of the Language Resources and Evaluation Conference\"}, {\"key\": \"watermark_llm\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"synthid_text\", \"type\": \"article\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"authors\": \"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"aaronson_watermark\", \"type\": \"misc\", \"title\": \"Watermarking GPT Outputs\", \"authors\": \"Aaronson, Scott and Kirchner, Hendrik\", \"year\": \"2022\", \"venue\": \"\"}, {\"key\": \"chainwash\", \"type\": \"article\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"authors\": \"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.05503\"}, {\"key\": \"curious_decline\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of the Association for Computational Linguistics: NAACL\"}, {\"key\": \"writing_diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"nucleus_sampling\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"stamatatos_survey\", \"type\": \"article\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"authors\": \"Stamatatos, Efstathios\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"koppel_authorship\", \"type\": \"article\", \"title\": \"Computational Methods in Authorship Attribution\", \"authors\": \"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"uchendu_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"munir_looking_glass\", \"type\": \"inproceedings\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"authors\": \"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\", \"year\": \"2021\", \"venue\": \"Proceedings of the Conference of the European Chapter of the Association for Com...\"}, {\"key\": \"broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"attractor_cycles\", \"type\": \"inproceedings\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"authors\": \"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"markovian_chains\", \"type\": \"article\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"authors\": \"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2603.11228\"}, {\"key\": \"min_k_percent\", \"type\": \"inproceedings\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"authors\": \"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"wu_survey_2025\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"jawahar_survey\", \"type\": \"inproceedings\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"authors\": \"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Computational Linguistics\"}, {\"key\": \"pythia\", \"type\": \"inproceedings\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"authors\": \"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"olmo\", \"type\": \"inproceedings\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"authors\": \"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"qwen3\", \"type\": \"article\", \"title\": \"Qwen3 Technical Report\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.09388\"}, {\"key\": \"ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"two_birds\", \"type\": \"article\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"authors\": \"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2508.14190\"}, {\"key\": \"beyond_final_actor\", \"type\": \"inproceedings\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"authors\": \"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\", \"year\": \"2026\", \"venue\": \"Proceedings of the Association for Computational Linguistics\"}, {\"key\": \"gutierrez_ordinal_survey\", \"type\": \"article\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"authors\": \"Guti\\\\'errez, Pedro Antonio and P\\\\'erez-Ortiz, Mar\\\\'ia and S\\\\'anchez-Monedero, Ja...\", \"year\": \"2016\", \"venue\": \"IEEE Transactions on Knowledge and Data Engineering\"}, {\"key\": \"coral_ordinal\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"frank_hall_ordinal\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of the European Conference on Machine Learning\"}, {\"key\": \"pang_opinion_mining\", \"type\": \"inproceedings\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"authors\": \"Pang, Bo and Lee, Lillian\", \"year\": \"2005\", \"venue\": \"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\"}, {\"key\": \"taghipour_neural_essay\", \"type\": \"inproceedings\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"authors\": \"Taghipour, Kaveh and Ng, Hwee Tou\", \"year\": \"2016\", \"venue\": \"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\"}, {\"key\": \"corn_ordinal\", \"type\": \"article\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"authors\": \"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\", \"year\": \"2023\", \"venue\": \"Pattern Analysis and Applications\"}, {\"key\": \"xgboost\", \"type\": \"inproceedings\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"authors\": \"Chen, Tianqi and Guestrin, Carlos\", \"year\": \"2016\", \"venue\": \"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\"}, {\"key\": \"lakens_equivalence\", \"type\": \"article\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"authors\": \"Lakens, Dani\\\\\\\"el\", \"year\": \"2017\", \"venue\": \"Social Psychological and Personality Science\"}, {\"key\": \"llama3\", \"type\": \"article\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2407.21783\"}, {\"key\": \"mistral7b\", \"type\": \"article\", \"title\": \"Mistral 7B\", \"authors\": \"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\", \"year\": \"2023\", \"venue\": \"arXiv preprint arXiv:2310.06825\"}, {\"key\": \"strobl_conditional_2008\", \"type\": \"article\", \"title\": \"Conditional Variable Importance for Random Forests\", \"authors\": \"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\", \"year\": \"2008\", \"venue\": \"BMC Bioinformatics\"}, {\"key\": \"zhu_beat_llms\", \"type\": \"inproceedings\", \"title\": \"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\", \"authors\": \"Zhu, Biru and Fang, Lifan and Sui, Jiayuan and Lu, Teng\", \"year\": \"2023\", \"venue\": \"Proceedings of the 2023 Conference on Empirical Methods in Natural Language Proc...\"}, {\"key\": \"dolma\", \"type\": \"inproceedings\", \"title\": \"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\", \"authors\": \"Soldaini, Luca and Kinney, Rodney and Bhagia, Akshita and Schwenk, Dustin and At...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"fineweb\", \"type\": \"inproceedings\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"authors\": \"\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems: Datasets and Benchmarks Track\"}, {\"key\": \"mapping_llm_science\", \"type\": \"inproceedings\", \"title\": \"Mapping the Increasing Use of LLMs in Scientific Papers\", \"authors\": \"Liang, Weixin and Zhang, Yaohui and Wu, Zhengxuan and Lepp, Haley and Ji, Wenlon...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Conference on Language Modeling\"}, {\"key\": \"monitoring_ai_review\", \"type\": \"inproceedings\", \"title\": \"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\", \"authors\": \"Liang, Weixin and Izzo, Zachary and Zhang, Yaohui and Lepp, Haley and Cao, Hanch...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"self_refine\", \"type\": \"inproceedings\", \"title\": \"Self-Refine: Iterative Refinement with Self-Feedback\", \"authors\": \"Madaan, Aman and Tandon, Niket and Gupta, Prakhar and Hallinan, Skyler and Gao, ...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"raid\", \"type\": \"inproceedings\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"authors\": \"Dugan, Liam and Hwang, Alyssa and Trhl\\\\'\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\", \"year\": \"2024\", \"venue\": \"Proceedings of the 62nd Annual Meeting of the Association for Computational Ling...\"}], \"tex_citations\": [{\"key\": \"curse_of_recursion\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"ccnet\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"dsir\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"dolma\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"fineweb\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"mapping_llm_science\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"monitoring_ai_review\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"markovian_chains\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"gltr\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"grover\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"release_strategies\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"dna_gpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ghostbuster\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"feat_aug_transformer\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"reliable_detection\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"intrinsic_dimension\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"diveye\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"generator_barrier\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"wu_survey_2025\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"citet\"}, {\"key\": \"jawahar_survey\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"citet\"}, {\"key\": \"beyond_binary\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"two_birds\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"beyond_final_actor\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"semeval2024_task8\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"paraphrase_evades\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"detection_possibilities\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"gutierrez_ordinal_survey\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"munir_looking_glass\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"model_collapse_avoidable\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"self_refine\", \"file\": \"related_work.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"curious_decline\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"writing_diversity\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"stamatatos_survey\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"koppel_authorship\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"nucleus_sampling\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"dsir\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"cite\"}, {\"key\": \"qurating\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"cite\"}, {\"key\": \"ccnet\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"cite\"}, {\"key\": \"watermark_llm\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"synthid_text\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"aaronson_watermark\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"chainwash\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"min_k_percent\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"citet\"}, {\"key\": \"pythia\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"olmo\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"qwen3\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"mistral7b\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"xgboost\", \"file\": \"method.tex\", \"line\": 87, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"method.tex\", \"line\": 89, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"method.tex\", \"line\": 89, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"method.tex\", \"line\": 98, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"method.tex\", \"line\": 98, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"method.tex\", \"line\": 98, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"results.tex\", \"line\": 75, \"command\": \"cite\"}, {\"key\": \"strobl_conditional_2008\", \"file\": \"results.tex\", \"line\": 89, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"discussion.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"curse_of_recursion\", \"file\": \"discussion.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"discussion.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"qlora\", \"file\": \"appendix_qlora.tex\", \"line\": 1, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_downstream.tex\", \"line\": 41, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_tost.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"appendix_tost.tex\", \"line\": 5, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"mccarthy2010mtld\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"covington2010mattr\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"status\": \"verified\", \"confidence\": 0.986, \"matched_title\": \"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"oren2024proving\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Proving Test Set Contamination in Black Box Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"golchin2024time\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"longpre2024data\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cohen1988statistical\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"matched_year\": \"1989\", \"mismatch_fields\": [\"first_author: bib=cohen vs api=muller\"], \"note\": \"\"}, {\"key\": \"tang2024science\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Science of Detecting LLM-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"neal2017surveying\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Surveying Stylometry Techniques and Applications\", \"matched_year\": \"2017\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dna_gpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fast_detectgpt\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ld_score\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"intrinsic_dimension\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"feat_aug_transformer\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"reliable_detection\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"status\": \"not_found\", \"confidence\": 0.344, \"matched_title\": \"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.34 below threshold 0.82\"}, {\"key\": \"paraphrase_evades\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detection_possibilities\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.253, \"matched_title\": \"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.25 below threshold 0.82\"}, {\"key\": \"grover\", \"title\": \"Defending Against Neural Fake News\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Defending Against Neural Fake News\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"release_strategies\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Release Strategies and the Social Impacts of Language Models\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"beyond_binary\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"semeval2024_task8\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"abburi_multifaceted\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"defactify_dataset\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.355, \"matched_title\": \"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.36 below threshold 0.82\"}, {\"key\": \"self_consuming_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"curse_of_recursion\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strong_model_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"model_collapse_avoidable\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"self_rewarding_lms\", \"title\": \"Self-Rewarding Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Rewarding Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"spin\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qlora\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"status\": \"verified\", \"confidence\": 0.871, \"matched_title\": \"QLoRA: Efficient Finetuning of Quantized LLMs\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dsir\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"watermark_llm\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthid_text\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Scalable watermarking for identifying large language model outputs\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"aaronson_watermark\", \"title\": \"Watermarking GPT Outputs\", \"status\": \"not_found\", \"confidence\": 0.418, \"matched_title\": \"Undetectable Watermarks for Language Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.42 below threshold 0.82\"}, {\"key\": \"chainwash\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"curious_decline\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"writing_diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"nucleus_sampling\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"stamatatos_survey\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A survey of modern authorship attribution methods\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"koppel_authorship\", \"title\": \"Computational Methods in Authorship Attribution\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Computational methods in authorship attribution\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"munir_looking_glass\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"attractor_cycles\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"markovian_chains\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Markovian Generation Chains in Large Language Models\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"min_k_percent\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Detecting Pretraining Data from Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wu_survey_2025\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"jawahar_survey\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pythia\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"status\": \"not_found\", \"confidence\": 0.497, \"matched_title\": \"The TRIPOD-LLM reporting guideline for studies using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"olmo\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"OLMo: Accelerating the Science of Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qwen3\", \"title\": \"Qwen3 Technical Report\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Qwen3 Technical Report\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=team vs api=yang\"], \"note\": \"\"}, {\"key\": \"ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"two_birds\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"status\": \"not_found\", \"confidence\": 0.32, \"matched_title\": \"Large AI Models in Health Informatics: Applications, Challenges, and the Future\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.32 below threshold 0.82\"}, {\"key\": \"beyond_final_actor\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.722, \"matched_title\": \"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.72 below threshold 0.82\"}, {\"key\": \"gutierrez_ordinal_survey\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"2015\", \"mismatch_fields\": [\"first_author: bib=guti\\\\'errez vs api=gutiérrez\"], \"note\": \"\"}, {\"key\": \"coral_ordinal\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank_hall_ordinal\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pang_opinion_mining\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\", \"matched_year\": \"2005\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"taghipour_neural_essay\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Neural Approach to Automated Essay Scoring\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"corn_ordinal\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"xgboost\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"status\": \"not_found\", \"confidence\": 0.298, \"matched_title\": \"XGBoost\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.30 below threshold 0.82\"}, {\"key\": \"lakens_equivalence\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"status\": \"verified\", \"confidence\": 0.976, \"matched_title\": \"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"mistral7b\", \"title\": \"Mistral 7B\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mistral 7B\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strobl_conditional_2008\", \"title\": \"Conditional Variable Importance for Random Forests\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Conditional variable importance for random forests\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"zhu_beat_llms\", \"title\": \"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dolma\", \"title\": \"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fineweb\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mapping_llm_science\", \"title\": \"Mapping the Increasing Use of LLMs in Scientific Papers\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mapping the Increasing Use of LLMs in Scientific Papers\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"monitoring_ai_review\", \"title\": \"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"self_refine\", \"title\": \"Self-Refine: Iterative Refinement with Self-Feedback\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Refine: Iterative Refinement with Self-Feedback\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"raid\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "ff9bb416-c645-4e5d-b0bd-104d9dcd33e3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
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
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "e263dbb8-47ab-48c7-bf87-242936589a5d",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Tool call

_source line 22 · 2026-05-20T02:54:53.827Z_

<details open><summary>🔧 Tool call — Read · `toolu_01U5B33ngeyVq3CuSjhd559s`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p1.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e263dbb8-47ab-48c7-bf87-242936589a5d",
  "isSidechain": false,
  "requestId": "req_011CbD4pm3LHe8bh9X4XEmPt",
  "type": "assistant",
  "uuid": "dc68e1f7-092b-4fac-ba1d-7b9fda05c4dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W9JujWbi2RPGsjTpgYc9kA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 29094,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 29094,
          "cache_creation_input_tokens": 1908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1908
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

_source line 23 · 2026-05-20T02:54:54.336Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WxkKmTzq43qf8tMgxVieaB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p2.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dc68e1f7-092b-4fac-ba1d-7b9fda05c4dd",
  "isSidechain": false,
  "requestId": "req_011CbD4pm3LHe8bh9X4XEmPt",
  "type": "assistant",
  "uuid": "e89caafb-c159-453d-ab01-bbf9ccdd0fd1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W9JujWbi2RPGsjTpgYc9kA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 29094,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 29094,
          "cache_creation_input_tokens": 1908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1908
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

_source line 24 · 2026-05-20T02:54:54.455Z_

<details><summary>↩ Tool result · `toolu_01U5B33ngeyVq3CuSjhd559s`</summary>

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
  "parentUuid": "dc68e1f7-092b-4fac-ba1d-7b9fda05c4dd",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "aaaa0256-218c-497c-b433-32a34e65bd8b",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 451877
    }
  },
  "sourceToolAssistantUUID": "dc68e1f7-092b-4fac-ba1d-7b9fda05c4dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-20T02:54:54.993Z_

<details><summary>↩ Tool result · `toolu_01WxkKmTzq43qf8tMgxVieaB`</summary>

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
  "parentUuid": "e89caafb-c159-453d-ab01-bbf9ccdd0fd1",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "a189e18b-dfee-4dfc-b18c-cae10d845da0",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 530578
    }
  },
  "sourceToolAssistantUUID": "e89caafb-c159-453d-ab01-bbf9ccdd0fd1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-20T02:54:55.405Z_

<details open><summary>🔧 Tool call — Read · `toolu_012qYPjVJp4iCXeSTp8qcKwb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p3.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a189e18b-dfee-4dfc-b18c-cae10d845da0",
  "isSidechain": false,
  "requestId": "req_011CbD4pm3LHe8bh9X4XEmPt",
  "type": "assistant",
  "uuid": "8ca65c7b-765d-44c0-9b07-d92a15721856",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W9JujWbi2RPGsjTpgYc9kA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 29094,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 29094,
          "cache_creation_input_tokens": 1908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1908
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

_source line 27 · 2026-05-20T02:54:55.885Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AQUwqyjgNjo9o7Ko7SWTQM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p4.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ca65c7b-765d-44c0-9b07-d92a15721856",
  "isSidechain": false,
  "requestId": "req_011CbD4pm3LHe8bh9X4XEmPt",
  "type": "assistant",
  "uuid": "7d2663b1-18f1-4cd9-a420-43a6e83c1f1f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W9JujWbi2RPGsjTpgYc9kA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 29094,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 29094,
          "cache_creation_input_tokens": 1908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1908
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

_source line 28 · 2026-05-20T02:54:56.088Z_

<details><summary>↩ Tool result · `toolu_012qYPjVJp4iCXeSTp8qcKwb`</summary>

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
  "parentUuid": "8ca65c7b-765d-44c0-9b07-d92a15721856",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "9472d2fe-7bd7-4bb2-bae4-e3b5f572751b",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 514865
    }
  },
  "sourceToolAssistantUUID": "8ca65c7b-765d-44c0-9b07-d92a15721856",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-20T02:54:56.346Z_

<details open><summary>🔧 Tool call — Read · `toolu_01V1c83UUYNGdXdHyHR3oSVS`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p5.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9472d2fe-7bd7-4bb2-bae4-e3b5f572751b",
  "isSidechain": false,
  "requestId": "req_011CbD4pm3LHe8bh9X4XEmPt",
  "type": "assistant",
  "uuid": "e9d7d320-2e5e-4313-af8c-1730727dd414",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W9JujWbi2RPGsjTpgYc9kA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 29094,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 29094,
          "cache_creation_input_tokens": 1908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1908
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

_source line 30 · 2026-05-20T02:54:56.722Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BXkGDaUe11gK3dUDQGprG9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p6.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e9d7d320-2e5e-4313-af8c-1730727dd414",
  "isSidechain": false,
  "requestId": "req_011CbD4pm3LHe8bh9X4XEmPt",
  "type": "assistant",
  "uuid": "c15d869b-b604-424a-a938-b4a4667e655c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W9JujWbi2RPGsjTpgYc9kA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 29094,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 29094,
          "cache_creation_input_tokens": 1908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1908
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

_source line 31_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "c15d869b-b604-424a-a938-b4a4667e655c",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 32_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Tool result

_source line 33 · 2026-05-20T02:54:57.581Z_

<details><summary>↩ Tool result · `toolu_01AQUwqyjgNjo9o7Ko7SWTQM`</summary>

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
  "parentUuid": "7d2663b1-18f1-4cd9-a420-43a6e83c1f1f",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "c492aa98-4b76-4046-8a22-cd49cfa0d610",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 510160
    }
  },
  "sourceToolAssistantUUID": "7d2663b1-18f1-4cd9-a420-43a6e83c1f1f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 34_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "c492aa98-4b76-4046-8a22-cd49cfa0d610",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 35_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Tool result

_source line 36 · 2026-05-20T02:54:58.562Z_

<details><summary>↩ Tool result · `toolu_01V1c83UUYNGdXdHyHR3oSVS`</summary>

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
  "parentUuid": "e9d7d320-2e5e-4313-af8c-1730727dd414",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "5da387d6-b76d-45c7-a7f0-a4e2ab1e43d4",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 527499
    }
  },
  "sourceToolAssistantUUID": "e9d7d320-2e5e-4313-af8c-1730727dd414",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 37_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "5da387d6-b76d-45c7-a7f0-a4e2ab1e43d4",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 38_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Tool result

_source line 39 · 2026-05-20T02:54:58.930Z_

<details><summary>↩ Tool result · `toolu_01BXkGDaUe11gK3dUDQGprG9`</summary>

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
  "parentUuid": "c15d869b-b604-424a-a938-b4a4667e655c",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "aa3897da-e89a-4aa8-bf6d-b9b5519d62f6",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 491229
    }
  },
  "sourceToolAssistantUUID": "c15d869b-b604-424a-a938-b4a4667e655c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 40 · 2026-05-20T02:54:58.936Z_

```json
{
  "parentUuid": "aa3897da-e89a-4aa8-bf6d-b9b5519d62f6",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "5e213ed4-dc37-469c-8150-2a635d149fa9",
  "timestamp": "2026-05-20T02:54:58.936Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 41_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "5e213ed4-dc37-469c-8150-2a635d149fa9",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 42_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Assistant

_source line 43 · 2026-05-20T02:55:03.106Z_

<details><summary>Logged reasoning block</summary>

```text
Let me continue reading the remaining pages of the paper. The paper has 31 pages total. I've read pages 1-6. Let me read pages 7-12 next.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5e213ed4-dc37-469c-8150-2a635d149fa9",
  "isSidechain": false,
  "requestId": "req_011CbD4qMaipE7kHweYMdfFr",
  "type": "assistant",
  "uuid": "0220ae4c-d1d2-4617-8eca-ed529f0443f8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MDHptC6b8E8pKXQDeRRyGT",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2902,
      "cache_read_input_tokens": 31002,
      "output_tokens": 228,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2902,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 228,
          "cache_read_input_tokens": 31002,
          "cache_creation_input_tokens": 2902,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2902
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

_source line 44 · 2026-05-20T02:55:04.046Z_

继续读取剩余页面。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0220ae4c-d1d2-4617-8eca-ed529f0443f8",
  "isSidechain": false,
  "requestId": "req_011CbD4qMaipE7kHweYMdfFr",
  "type": "assistant",
  "uuid": "d3bdf1aa-5b55-4e2f-a2ca-d07640467508",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MDHptC6b8E8pKXQDeRRyGT",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2902,
      "cache_read_input_tokens": 31002,
      "output_tokens": 228,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2902,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 228,
          "cache_read_input_tokens": 31002,
          "cache_creation_input_tokens": 2902,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2902
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

_source line 45 · 2026-05-20T02:55:06.366Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01DarsB28housPVUuDaJnGj1`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf",
  "project": "gen-depth-fingerprint",
  "pages": "7-12",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d3bdf1aa-5b55-4e2f-a2ca-d07640467508",
  "isSidechain": false,
  "requestId": "req_011CbD4qMaipE7kHweYMdfFr",
  "type": "assistant",
  "uuid": "e722e13f-1540-4574-b35a-8e3f737a8149",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MDHptC6b8E8pKXQDeRRyGT",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2902,
      "cache_read_input_tokens": 31002,
      "output_tokens": 228,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2902,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 228,
          "cache_read_input_tokens": 31002,
          "cache_creation_input_tokens": 2902,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2902
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

_source line 46 · 2026-05-20T02:55:07.021Z_

<details><summary>↩ Tool result · `toolu_01DarsB28housPVUuDaJnGj1`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"images\": [{\"page\": 7, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p7.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 510.2}, {\"page\": 8, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p8.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 493.1}, {\"page\": 9, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p9.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 518.1}, {\"page\": 10, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p10.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 555.9}, {\"page\": 11, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p11.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 547.3}, {\"page\": 12, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p12.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 543.9}], \"total_pages\": 31, \"rendered_pages\": 6, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e722e13f-1540-4574-b35a-8e3f737a8149",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "c61dc9dd-94c8-4514-a2d9-75691a7ea96d",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"images\\\": [{\\\"page\\\": 7, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p7.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 510.2}, {\\\"page\\\": 8, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p8.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 493.1}, {\\\"page\\\": 9, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p9.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 518.1}, {\\\"page\\\": 10, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p10.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 555.9}, {\\\"page\\\": 11, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p11.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 547.3}, {\\\"page\\\": 12, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p12.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 543.9}], \\\"total_pages\\\": 31, \\\"rendered_pages\\\": 6, \\\"dpi\\\": 150, \\\"output_dir\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"images\": [{\"page\": 7, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p7.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 510.2}, {\"page\": 8, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p8.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 493.1}, {\"page\": 9, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p9.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 518.1}, {\"page\": 10, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p10.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 555.9}, {\"page\": 11, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p11.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 547.3}, {\"page\": 12, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p12.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 543.9}], \"total_pages\": 31, \"rendered_pages\": 6, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "e722e13f-1540-4574-b35a-8e3f737a8149",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-20T02:55:09.916Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Ai2sNfzEQTkr9b5JPThRJb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p7.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c61dc9dd-94c8-4514-a2d9-75691a7ea96d",
  "isSidechain": false,
  "requestId": "req_011CbD4qxEKHKREWRH9uMnMD",
  "type": "assistant",
  "uuid": "dd0e07c1-afe8-485b-b05c-629599d7d3dc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AnhxY8DvmYwDL9MvsYoUVW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 869,
      "cache_read_input_tokens": 33904,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 869,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 33904,
          "cache_creation_input_tokens": 869,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 869
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

_source line 48 · 2026-05-20T02:55:10.412Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UoxV8hZ3MVvbyaDU6SVhvB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p8.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dd0e07c1-afe8-485b-b05c-629599d7d3dc",
  "isSidechain": false,
  "requestId": "req_011CbD4qxEKHKREWRH9uMnMD",
  "type": "assistant",
  "uuid": "dd378e90-cc54-412c-b87e-9c0482baba6a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AnhxY8DvmYwDL9MvsYoUVW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 869,
      "cache_read_input_tokens": 33904,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 869,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 33904,
          "cache_creation_input_tokens": 869,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 869
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

_source line 49 · 2026-05-20T02:55:10.528Z_

<details><summary>↩ Tool result · `toolu_01Ai2sNfzEQTkr9b5JPThRJb`</summary>

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
  "parentUuid": "dd0e07c1-afe8-485b-b05c-629599d7d3dc",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "cf814fc9-d8df-4cb4-a2d3-5f22672335f6",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 522492
    }
  },
  "sourceToolAssistantUUID": "dd0e07c1-afe8-485b-b05c-629599d7d3dc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 50 · 2026-05-20T02:55:11.065Z_

<details><summary>↩ Tool result · `toolu_01UoxV8hZ3MVvbyaDU6SVhvB`</summary>

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
  "parentUuid": "dd378e90-cc54-412c-b87e-9c0482baba6a",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "8494bad4-557a-4102-934f-3c3ad41e76d7",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 504955
    }
  },
  "sourceToolAssistantUUID": "dd378e90-cc54-412c-b87e-9c0482baba6a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 51 · 2026-05-20T02:55:11.335Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JJqKk9TojjEiFHu7rDHhip`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p9.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8494bad4-557a-4102-934f-3c3ad41e76d7",
  "isSidechain": false,
  "requestId": "req_011CbD4qxEKHKREWRH9uMnMD",
  "type": "assistant",
  "uuid": "98bbd4ee-5511-46c5-b744-83aa8b162d4f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AnhxY8DvmYwDL9MvsYoUVW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 869,
      "cache_read_input_tokens": 33904,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 869,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 33904,
          "cache_creation_input_tokens": 869,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 869
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

_source line 52 · 2026-05-20T02:55:11.840Z_

<details open><summary>🔧 Tool call — Read · `toolu_01C3FBr511h29eQdw8A3msQM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p10.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "98bbd4ee-5511-46c5-b744-83aa8b162d4f",
  "isSidechain": false,
  "requestId": "req_011CbD4qxEKHKREWRH9uMnMD",
  "type": "assistant",
  "uuid": "a17b0d3b-4b67-4976-9179-e1712aba318d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AnhxY8DvmYwDL9MvsYoUVW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 869,
      "cache_read_input_tokens": 33904,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 869,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 33904,
          "cache_creation_input_tokens": 869,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 869
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

_source line 53 · 2026-05-20T02:55:11.957Z_

<details><summary>↩ Tool result · `toolu_01JJqKk9TojjEiFHu7rDHhip`</summary>

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
  "parentUuid": "98bbd4ee-5511-46c5-b744-83aa8b162d4f",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "2deff729-77d4-4a2b-8052-3d38424ff75b",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 530555
    }
  },
  "sourceToolAssistantUUID": "98bbd4ee-5511-46c5-b744-83aa8b162d4f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-20T02:55:12.330Z_

<details open><summary>🔧 Tool call — Read · `toolu_019poRSWCjirATHNK5awUxBF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p11.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2deff729-77d4-4a2b-8052-3d38424ff75b",
  "isSidechain": false,
  "requestId": "req_011CbD4qxEKHKREWRH9uMnMD",
  "type": "assistant",
  "uuid": "1ceb2677-f4df-47d0-944f-5f46e690ad85",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AnhxY8DvmYwDL9MvsYoUVW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 869,
      "cache_read_input_tokens": 33904,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 869,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 33904,
          "cache_creation_input_tokens": 869,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 869
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

_source line 55 · 2026-05-20T02:55:12.539Z_

<details><summary>↩ Tool result · `toolu_01C3FBr511h29eQdw8A3msQM`</summary>

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
  "parentUuid": "a17b0d3b-4b67-4976-9179-e1712aba318d",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "143580a8-eee5-4163-a568-5e15dcbe3a10",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 569251
    }
  },
  "sourceToolAssistantUUID": "a17b0d3b-4b67-4976-9179-e1712aba318d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 56 · 2026-05-20T02:55:12.691Z_

<details open><summary>🔧 Tool call — Read · `toolu_01ExHH3trqHHrY7dJ6dm6fJp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p12.png"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "143580a8-eee5-4163-a568-5e15dcbe3a10",
  "isSidechain": false,
  "requestId": "req_011CbD4qxEKHKREWRH9uMnMD",
  "type": "assistant",
  "uuid": "99b40261-e134-4103-b083-2814d237b00a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AnhxY8DvmYwDL9MvsYoUVW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 869,
      "cache_read_input_tokens": 33904,
      "output_tokens": 497,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 869,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 497,
          "cache_read_input_tokens": 33904,
          "cache_creation_input_tokens": 869,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 869
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

_source line 57_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "99b40261-e134-4103-b083-2814d237b00a",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 58_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Tool result

_source line 59 · 2026-05-20T02:55:13.400Z_

<details><summary>↩ Tool result · `toolu_019poRSWCjirATHNK5awUxBF`</summary>

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
  "parentUuid": "1ceb2677-f4df-47d0-944f-5f46e690ad85",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "b218f09c-c92d-4909-85e8-95d1655a2f21",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 560439
    }
  },
  "sourceToolAssistantUUID": "1ceb2677-f4df-47d0-944f-5f46e690ad85",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 60_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "b218f09c-c92d-4909-85e8-95d1655a2f21",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 61_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Tool result

_source line 62 · 2026-05-20T02:55:13.590Z_

<details><summary>↩ Tool result · `toolu_01ExHH3trqHHrY7dJ6dm6fJp`</summary>

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
  "parentUuid": "99b40261-e134-4103-b083-2814d237b00a",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "a124b45b-378a-4dcb-aef9-106e3ab19dc9",
  "toolUseResult": {
    "type": "image",
    "file": {
      "base64": "[ATTACHMENT_DATA_REDACTED]",
      "type": "image/jpeg",
      "originalSize": 556926
    }
  },
  "sourceToolAssistantUUID": "99b40261-e134-4103-b083-2814d237b00a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 63_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "a124b45b-378a-4dcb-aef9-106e3ab19dc9",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 64_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Assistant

_source line 65 · 2026-05-20T02:55:20.869Z_

<details><summary>Logged reasoning block</summary>

```text
Let me continue reading the appendix pages and also read the reference verification results more carefully. Let me get pages 13-20 and also read the full reference verification output.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a124b45b-378a-4dcb-aef9-106e3ab19dc9",
  "isSidechain": false,
  "requestId": "req_011CbD4rSFJ8xbaexSmeRrHq",
  "type": "assistant",
  "uuid": "b0b7893e-134e-4448-b800-275b3f5d1e2c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JKZbzCvFbT4JnTMi8GdHQj",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2796,
      "cache_read_input_tokens": 34773,
      "output_tokens": 387,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2796,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 387,
          "cache_read_input_tokens": 34773,
          "cache_creation_input_tokens": 2796,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2796
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

_source line 66 · 2026-05-20T02:55:22.325Z_

继续读取附录部分。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b0b7893e-134e-4448-b800-275b3f5d1e2c",
  "isSidechain": false,
  "requestId": "req_011CbD4rSFJ8xbaexSmeRrHq",
  "type": "assistant",
  "uuid": "3e469529-0a48-471b-a5c3-b19d802dcbd9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JKZbzCvFbT4JnTMi8GdHQj",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2796,
      "cache_read_input_tokens": 34773,
      "output_tokens": 387,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2796,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 387,
          "cache_read_input_tokens": 34773,
          "cache_creation_input_tokens": 2796,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2796
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

_source line 67 · 2026-05-20T02:55:24.703Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01RjseqDQzt7hLiasApQm4t9`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf",
  "project": "gen-depth-fingerprint",
  "pages": "13-20",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3e469529-0a48-471b-a5c3-b19d802dcbd9",
  "isSidechain": false,
  "requestId": "req_011CbD4rSFJ8xbaexSmeRrHq",
  "type": "assistant",
  "uuid": "d377b10f-bab4-4c7f-944e-2dcb42c288ab",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JKZbzCvFbT4JnTMi8GdHQj",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2796,
      "cache_read_input_tokens": 34773,
      "output_tokens": 387,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2796,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 387,
          "cache_read_input_tokens": 34773,
          "cache_creation_input_tokens": 2796,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2796
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

_source line 68 · 2026-05-20T02:55:25.717Z_

<details><summary>↩ Tool result · `toolu_01RjseqDQzt7hLiasApQm4t9`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"images\": [{\"page\": 13, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p13.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 158.9}, {\"page\": 14, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p14.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 184.1}, {\"page\": 15, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p15.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 442.9}, {\"page\": 16, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p16.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 497.4}, {\"page\": 17, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p17.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 444.3}, {\"page\": 18, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p18.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 449.5}, {\"page\": 19, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p19.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 479.8}, {\"page\": 20, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p20.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 483.6}], \"total_pages\": 31, \"rendered_pages\": 8, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d377b10f-bab4-4c7f-944e-2dcb42c288ab",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "550e80ca-dc41-4414-b17a-81fdf1cabcbc",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"images\\\": [{\\\"page\\\": 13, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p13.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 158.9}, {\\\"page\\\": 14, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p14.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 184.1}, {\\\"page\\\": 15, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p15.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 442.9}, {\\\"page\\\": 16, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p16.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 497.4}, {\\\"page\\\": 17, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p17.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 444.3}, {\\\"page\\\": 18, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p18.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 449.5}, {\\\"page\\\": 19, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p19.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 479.8}, {\\\"page\\\": 20, \\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p20.png\\\", \\\"width\\\": 1241, \\\"height\\\": 1754, \\\"size_kb\\\": 483.6}], \\\"total_pages\\\": 31, \\\"rendered_pages\\\": 8, \\\"dpi\\\": 150, \\\"output_dir\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"images\": [{\"page\": 13, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p13.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 158.9}, {\"page\": 14, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p14.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 184.1}, {\"page\": 15, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p15.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 442.9}, {\"page\": 16, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p16.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 497.4}, {\"page\": 17, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p17.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 444.3}, {\"page\": 18, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p18.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 449.5}, {\"page\": 19, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p19.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 479.8}, {\"page\": 20, \"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images/main_p20.png\", \"width\": 1241, \"height\": 1754, \"size_kb\": 483.6}], \"total_pages\": 31, \"rendered_pages\": 8, \"dpi\": 150, \"output_dir\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/_pdf_images\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "d377b10f-bab4-4c7f-944e-2dcb42c288ab",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 69 · 2026-05-20T02:55:29.470Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JoDadzsEhE1BoUQUMLPCvA`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/066b279c-ffce-4f4d-ae71-63c4ec55d181/tool-results/toolu_01UGGT4E2LpZpPzBZZMDtA8h.txt",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "550e80ca-dc41-4414-b17a-81fdf1cabcbc",
  "isSidechain": false,
  "requestId": "req_011CbD4rSFJ8xbaexSmeRrHq",
  "type": "assistant",
  "uuid": "ad043d75-29f3-433b-a350-e03cba2dc94c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JKZbzCvFbT4JnTMi8GdHQj",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2796,
      "cache_read_input_tokens": 34773,
      "output_tokens": 387,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2796,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 387,
          "cache_read_input_tokens": 34773,
          "cache_creation_input_tokens": 2796,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2796
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

_source line 70 · 2026-05-20T02:55:29.718Z_

<details><summary>↩ Tool result · `toolu_01JoDadzsEhE1BoUQUMLPCvA`</summary>

```text
1	{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 78, \"total_citations\": 85, \"unique_cited_keys\": 61, \"orphan_bib\": 17, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 64, \"online_not_found\": 9, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [\"abburi_multifaceted\", \"attractor_cycles\", \"corn_ordinal\", \"covington2010mattr\", \"defactify_dataset\", \"golchin2024time\", \"longpre2024data\", \"mccarthy2010mtld\", \"neal2017surveying\", \"oren2024proving\", \"pang_opinion_mining\", \"raid\", \"self_rewarding_lms\", \"spin\", \"taghipour_neural_essay\", \"tang2024science\", \"zhu_beat_llms\"], \"missing_bib\": [], \"orphan_count\": 17, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"mccarthy2010mtld\", \"type\": \"article\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"authors\": \"McCarthy, Philip M. and Jarvis, Scott\", \"year\": \"2010\", \"venue\": \"Behavior Research Methods\"}, {\"key\": \"covington2010mattr\", \"type\": \"article\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"authors\": \"Covington, Michael A. and McFall, Joe D.\", \"year\": \"2010\", \"venue\": \"Journal of Quantitative Linguistics\"}, {\"key\": \"oren2024proving\", \"type\": \"inproceedings\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"authors\": \"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"golchin2024time\", \"type\": \"inproceedings\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"authors\": \"Golchin, Shahriar and Surdeanu, Mihai\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"longpre2024data\", \"type\": \"inproceedings\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"authors\": \"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"cohen1988statistical\", \"type\": \"book\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"authors\": \"Cohen, Jacob\", \"year\": \"1988\", \"venue\": \"\"}, {\"key\": \"tang2024science\", \"type\": \"article\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"authors\": \"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\", \"year\": \"2024\", \"venue\": \"Communications of the ACM\"}, {\"key\": \"neal2017surveying\", \"type\": \"article\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"authors\": \"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\", \"year\": \"2017\", \"venue\": \"ACM Computing Surveys\"}, {\"key\": \"detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"dna_gpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"binoculars\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"fast_detectgpt\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"ld_score\", \"type\": \"article\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"authors\": \"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.01647\"}, {\"key\": \"intrinsic_dimension\", \"type\": \"inproceedings\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"authors\": \"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"diveye\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"generator_barrier\", \"type\": \"article\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2604.13692\"}, {\"key\": \"feat_aug_transformer\", \"type\": \"article\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"authors\": \"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\"orn\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.03969\"}, {\"key\": \"reliable_detection\", \"type\": \"article\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2025\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"paraphrase_evades\", \"type\": \"inproceedings\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"authors\": \"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"detection_possibilities\", \"type\": \"inproceedings\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"authors\": \"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"grover\", \"type\": \"inproceedings\", \"title\": \"Defending Against Neural Fake News\", \"authors\": \"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\", \"year\": \"2019\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"release_strategies\", \"type\": \"article\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"authors\": \"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1908.09203\"}, {\"key\": \"beyond_binary\", \"type\": \"inproceedings\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"authors\": \"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\", \"year\": \"2025\", \"venue\": \"Proceedings of the ACM Web Conference\"}, {\"key\": \"semeval2024_task8\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Workshop on Semantic Evaluation\"}, {\"key\": \"abburi_multifaceted\", \"type\": \"article\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"authors\": \"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.11550\"}, {\"key\": \"defactify_dataset\", \"type\": \"article\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"authors\": \"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2510.22874\"}, {\"key\": \"self_consuming_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"curse_of_recursion\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"strong_model_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"model_collapse_avoidable\", \"type\": \"inproceedings\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"Proceedings of the First Conference on Language Modeling (COLM)\"}, {\"key\": \"self_rewarding_lms\", \"type\": \"article\", \"title\": \"Self-Rewarding Language Models\", \"authors\": \"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2401.10020\"}, {\"key\": \"spin\", \"type\": \"inproceedings\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"authors\": \"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\", \"year\": \"2024\", \"venue\": \"Proceedings of the 41st International Conference on Machine Learning\"}, {\"key\": \"qlora\", \"type\": \"inproceedings\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"authors\": \"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"dsir\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"qurating\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of the Language Resources and Evaluation Conference\"}, {\"key\": \"watermark_llm\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"synthid_text\", \"type\": \"article\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"authors\": \"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"aaronson_watermark\", \"type\": \"misc\", \"title\": \"Watermarking GPT Outputs\", \"authors\": \"Aaronson, Scott and Kirchner, Hendrik\", \"year\": \"2022\", \"venue\": \"\"}, {\"key\": \"chainwash\", \"type\": \"article\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"authors\": \"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.05503\"}, {\"key\": \"curious_decline\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of the Association for Computational Linguistics: NAACL\"}, {\"key\": \"writing_diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"nucleus_sampling\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"stamatatos_survey\", \"type\": \"article\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"authors\": \"Stamatatos, Efstathios\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"koppel_authorship\", \"type\": \"article\", \"title\": \"Computational Methods in Authorship Attribution\", \"authors\": \"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"uchendu_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"munir_looking_glass\", \"type\": \"inproceedings\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"authors\": \"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\", \"year\": \"2021\", \"venue\": \"Proceedings of the Conference of the European Chapter of the Association for Com...\"}, {\"key\": \"broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"attractor_cycles\", \"type\": \"inproceedings\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"authors\": \"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"markovian_chains\", \"type\": \"article\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"authors\": \"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2603.11228\"}, {\"key\": \"min_k_percent\", \"type\": \"inproceedings\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"authors\": \"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"wu_survey_2025\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"jawahar_survey\", \"type\": \"inproceedings\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"authors\": \"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Computational Linguistics\"}, {\"key\": \"pythia\", \"type\": \"inproceedings\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"authors\": \"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"olmo\", \"type\": \"inproceedings\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"authors\": \"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"qwen3\", \"type\": \"article\", \"title\": \"Qwen3 Technical Report\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.09388\"}, {\"key\": \"ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"two_birds\", \"type\": \"article\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"authors\": \"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2508.14190\"}, {\"key\": \"beyond_final_actor\", \"type\": \"inproceedings\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"authors\": \"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\", \"year\": \"2026\", \"venue\": \"Proceedings of the Association for Computational Linguistics\"}, {\"key\": \"gutierrez_ordinal_survey\", \"type\": \"article\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"authors\": \"Guti\\\\'errez, Pedro Antonio and P\\\\'erez-Ortiz, Mar\\\\'ia and S\\\\'anchez-Monedero, Ja...\", \"year\": \"2016\", \"venue\": \"IEEE Transactions on Knowledge and Data Engineering\"}, {\"key\": \"coral_ordinal\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"frank_hall_ordinal\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of the European Conference on Machine Learning\"}, {\"key\": \"pang_opinion_mining\", \"type\": \"inproceedings\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"authors\": \"Pang, Bo and Lee, Lillian\", \"year\": \"2005\", \"venue\": \"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\"}, {\"key\": \"taghipour_neural_essay\", \"type\": \"inproceedings\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"authors\": \"Taghipour, Kaveh and Ng, Hwee Tou\", \"year\": \"2016\", \"venue\": \"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\"}, {\"key\": \"corn_ordinal\", \"type\": \"article\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"authors\": \"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\", \"year\": \"2023\", \"venue\": \"Pattern Analysis and Applications\"}, {\"key\": \"xgboost\", \"type\": \"inproceedings\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"authors\": \"Chen, Tianqi and Guestrin, Carlos\", \"year\": \"2016\", \"venue\": \"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\"}, {\"key\": \"lakens_equivalence\", \"type\": \"article\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"authors\": \"Lakens, Dani\\\\\\\"el\", \"year\": \"2017\", \"venue\": \"Social Psychological and Personality Science\"}, {\"key\": \"llama3\", \"type\": \"article\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2407.21783\"}, {\"key\": \"mistral7b\", \"type\": \"article\", \"title\": \"Mistral 7B\", \"authors\": \"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\", \"year\": \"2023\", \"venue\": \"arXiv preprint arXiv:2310.06825\"}, {\"key\": \"strobl_conditional_2008\", \"type\": \"article\", \"title\": \"Conditional Variable Importance for Random Forests\", \"authors\": \"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\", \"year\": \"2008\", \"venue\": \"BMC Bioinformatics\"}, {\"key\": \"zhu_beat_llms\", \"type\": \"inproceedings\", \"title\": \"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\", \"authors\": \"Zhu, Biru and Fang, Lifan and Sui, Jiayuan and Lu, Teng\", \"year\": \"2023\", \"venue\": \"Proceedings of the 2023 Conference on Empirical Methods in Natural Language Proc...\"}, {\"key\": \"dolma\", \"type\": \"inproceedings\", \"title\": \"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\", \"authors\": \"Soldaini, Luca and Kinney, Rodney and Bhagia, Akshita and Schwenk, Dustin and At...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"fineweb\", \"type\": \"inproceedings\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"authors\": \"\", \"year\": \"2024\", \"venue\": \"Advances in Neural Information Processing Systems: Datasets and Benchmarks Track\"}, {\"key\": \"mapping_llm_science\", \"type\": \"inproceedings\", \"title\": \"Mapping the Increasing Use of LLMs in Scientific Papers\", \"authors\": \"Liang, Weixin and Zhang, Yaohui and Wu, Zhengxuan and Lepp, Haley and Ji, Wenlon...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Conference on Language Modeling\"}, {\"key\": \"monitoring_ai_review\", \"type\": \"inproceedings\", \"title\": \"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\", \"authors\": \"Liang, Weixin and Izzo, Zachary and Zhang, Yaohui and Lepp, Haley and Cao, Hanch...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"self_refine\", \"type\": \"inproceedings\", \"title\": \"Self-Refine: Iterative Refinement with Self-Feedback\", \"authors\": \"Madaan, Aman and Tandon, Niket and Gupta, Prakhar and Hallinan, Skyler and Gao, ...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"raid\", \"type\": \"inproceedings\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"authors\": \"Dugan, Liam and Hwang, Alyssa and Trhl\\\\'\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\", \"year\": \"2024\", \"venue\": \"Proceedings of the 62nd Annual Meeting of the Association for Computational Ling...\"}], \"tex_citations\": [{\"key\": \"curse_of_recursion\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"ccnet\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"dsir\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"dolma\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"fineweb\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"mapping_llm_science\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"monitoring_ai_review\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"introduction.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"markovian_chains\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"gltr\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"grover\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"release_strategies\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"dna_gpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ghostbuster\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"feat_aug_transformer\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"reliable_detection\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"intrinsic_dimension\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"diveye\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"generator_barrier\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"wu_survey_2025\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"citet\"}, {\"key\": \"jawahar_survey\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"citet\"}, {\"key\": \"beyond_binary\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"two_birds\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"beyond_final_actor\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"semeval2024_task8\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"paraphrase_evades\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"detection_possibilities\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"gutierrez_ordinal_survey\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"munir_looking_glass\", \"file\": \"related_work.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"model_collapse_avoidable\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"related_work.tex\", \"line\": 14, \"command\": \"cite\"}, {\"key\": \"self_refine\", \"file\": \"related_work.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"cite\"}, {\"key\": \"curious_decline\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"writing_diversity\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"stamatatos_survey\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"koppel_authorship\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"nucleus_sampling\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"dsir\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"cite\"}, {\"key\": \"qurating\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"cite\"}, {\"key\": \"ccnet\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"cite\"}, {\"key\": \"watermark_llm\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"synthid_text\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"aaronson_watermark\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"chainwash\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"cite\"}, {\"key\": \"min_k_percent\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"citet\"}, {\"key\": \"pythia\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"olmo\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"qwen3\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"mistral7b\", \"file\": \"method.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"xgboost\", \"file\": \"method.tex\", \"line\": 87, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"method.tex\", \"line\": 89, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"method.tex\", \"line\": 89, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"method.tex\", \"line\": 98, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"method.tex\", \"line\": 98, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"method.tex\", \"line\": 98, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"results.tex\", \"line\": 75, \"command\": \"cite\"}, {\"key\": \"strobl_conditional_2008\", \"file\": \"results.tex\", \"line\": 89, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"discussion.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"curse_of_recursion\", \"file\": \"discussion.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"discussion.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"qlora\", \"file\": \"appendix_qlora.tex\", \"line\": 1, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_downstream.tex\", \"line\": 41, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_tost.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"appendix_tost.tex\", \"line\": 5, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"mccarthy2010mtld\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"covington2010mattr\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"status\": \"verified\", \"confidence\": 0.986, \"matched_title\": \"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"oren2024proving\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Proving Test Set Contamination in Black Box Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"golchin2024time\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"longpre2024data\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cohen1988statistical\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"matched_year\": \"1989\", \"mismatch_fields\": [\"first_author: bib=cohen vs api=muller\"], \"note\": \"\"}, {\"key\": \"tang2024science\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Science of Detecting LLM-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"neal2017surveying\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Surveying Stylometry Techniques and Applications\", \"matched_year\": \"2017\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dna_gpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fast_detectgpt\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ld_score\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"intrinsic_dimension\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"feat_aug_transformer\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"reliable_detection\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"status\": \"not_found\", \"confidence\": 0.344, \"matched_title\": \"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.34 below threshold 0.82\"}, {\"key\": \"paraphrase_evades\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detection_possibilities\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.253, \"matched_title\": \"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.25 below threshold 0.82\"}, {\"key\": \"grover\", \"title\": \"Defending Against Neural Fake News\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Defending Against Neural Fake News\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"release_strategies\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Release Strategies and the Social Impacts of Language Models\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"beyond_binary\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"semeval2024_task8\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"abburi_multifaceted\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"defactify_dataset\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.355, \"matched_title\": \"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.36 below threshold 0.82\"}, {\"key\": \"self_consuming_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"curse_of_recursion\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strong_model_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"model_collapse_avoidable\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"self_rewarding_lms\", \"title\": \"Self-Rewarding Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Rewarding Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"spin\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qlora\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"status\": \"verified\", \"confidence\": 0.871, \"matched_title\": \"QLoRA: Efficient Finetuning of Quantized LLMs\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dsir\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"watermark_llm\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthid_text\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Scalable watermarking for identifying large language model outputs\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"aaronson_watermark\", \"title\": \"Watermarking GPT Outputs\", \"status\": \"not_found\", \"confidence\": 0.418, \"matched_title\": \"Undetectable Watermarks for Language Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.42 below threshold 0.82\"}, {\"key\": \"chainwash\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"curious_decline\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"writing_diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"nucleus_sampling\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"stamatatos_survey\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A survey of modern authorship attribution methods\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"koppel_authorship\", \"title\": \"Computational Methods in Authorship Attribution\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Computational methods in authorship attribution\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"munir_looking_glass\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"attractor_cycles\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"markovian_chains\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Markovian Generation Chains in Large Language Models\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"min_k_percent\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Detecting Pretraining Data from Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wu_survey_2025\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"jawahar_survey\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pythia\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"status\": \"not_found\", \"confidence\": 0.497, \"matched_title\": \"The TRIPOD-LLM reporting guideline for studies using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"olmo\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"OLMo: Accelerating the Science of Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qwen3\", \"title\": \"Qwen3 Technical Report\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Qwen3 Technical Report\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=team vs api=yang\"], \"note\": \"\"}, {\"key\": \"ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"two_birds\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"status\": \"not_found\", \"confidence\": 0.32, \"matched_title\": \"Large AI Models in Health Informatics: Applications, Challenges, and the Future\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.32 below threshold 0.82\"}, {\"key\": \"beyond_final_actor\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.722, \"matched_title\": \"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.72 below threshold 0.82\"}, {\"key\": \"gutierrez_ordinal_survey\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"2015\", \"mismatch_fields\": [\"first_author: bib=guti\\\\'errez vs api=gutiérrez\"], \"note\": \"\"}, {\"key\": \"coral_ordinal\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank_hall_ordinal\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pang_opinion_mining\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\", \"matched_year\": \"2005\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"taghipour_neural_essay\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Neural Approach to Automated Essay Scoring\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"corn_ordinal\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"xgboost\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"status\": \"not_found\", \"confidence\": 0.298, \"matched_title\": \"XGBoost\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.30 below threshold 0.82\"}, {\"key\": \"lakens_equivalence\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"status\": \"verified\", \"confidence\": 0.976, \"matched_title\": \"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"mistral7b\", \"title\": \"Mistral 7B\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mistral 7B\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strobl_conditional_2008\", \"title\": \"Conditional Variable Importance for Random Forests\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Conditional variable importance for random forests\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"zhu_beat_llms\", \"title\": \"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dolma\", \"title\": \"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fineweb\", \"title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mapping_llm_science\", \"title\": \"Mapping the Increasing Use of LLMs in Scientific Papers\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mapping the Increasing Use of LLMs in Scientific Papers\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"monitoring_ai_review\", \"title\": \"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"self_refine\", \"title\": \"Self-Refine: Iterative Refinement with Self-Feedback\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Refine: Iterative Refinement with Self-Feedback\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"raid\", \"title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ad043d75-29f3-433b-a350-e03cba2dc94c",
  "isSidechain": false,
  "promptId": "5451ac9c-469a-4a1d-96fe-a391bfa6b106",
  "type": "user",
  "uuid": "a38f4959-81c1-42e2-a720-cf512fcbb8cd",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/066b279c-ffce-4f4d-ae71-63c4ec55d181/tool-results/toolu_01UGGT4E2LpZpPzBZZMDtA8h.txt",
      "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 78, \\\"total_citations\\\": 85, \\\"unique_cited_keys\\\": 61, \\\"orphan_bib\\\": 17, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 64, \\\"online_not_found\\\": 9, \\\"online_mismatch\\\": 5}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [\\\"abburi_multifaceted\\\", \\\"attractor_cycles\\\", \\\"corn_ordinal\\\", \\\"covington2010mattr\\\", \\\"defactify_dataset\\\", \\\"golchin2024time\\\", \\\"longpre2024data\\\", \\\"mccarthy2010mtld\\\", \\\"neal2017surveying\\\", \\\"oren2024proving\\\", \\\"pang_opinion_mining\\\", \\\"raid\\\", \\\"self_rewarding_lms\\\", \\\"spin\\\", \\\"taghipour_neural_essay\\\", \\\"tang2024science\\\", \\\"zhu_beat_llms\\\"], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 17, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"authors\\\": \\\"McCarthy, Philip M. and Jarvis, Scott\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Behavior Research Methods\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"authors\\\": \\\"Covington, Michael A. and McFall, Joe D.\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Journal of Quantitative Linguistics\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"authors\\\": \\\"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"authors\\\": \\\"Golchin, Shahriar and Surdeanu, Mihai\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"authors\\\": \\\"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"type\\\": \\\"book\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"authors\\\": \\\"Cohen, Jacob\\\", \\\"year\\\": \\\"1988\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"authors\\\": \\\"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Communications of the ACM\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"authors\\\": \\\"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"ACM Computing Surveys\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"authors\\\": \\\"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.01647\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"authors\\\": \\\"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2604.13692\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"authors\\\": \\\"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\\\\\\\\\"orn\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.03969\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"authors\\\": \\\"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"authors\\\": \\\"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"authors\\\": \\\"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1908.09203\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"authors\\\": \\\"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the ACM Web Conference\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Workshop on Semantic Evaluation\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"authors\\\": \\\"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.11550\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"authors\\\": \\\"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2510.22874\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the First Conference on Language Modeling (COLM)\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"authors\\\": \\\"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2401.10020\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"authors\\\": \\\"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 41st International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"authors\\\": \\\"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Language Resources and Evaluation Conference\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"authors\\\": \\\"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"authors\\\": \\\"Aaronson, Scott and Kirchner, Hendrik\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"authors\\\": \\\"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.05503\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of the Association for Computational Linguistics: NAACL\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"authors\\\": \\\"Stamatatos, Efstathios\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"authors\\\": \\\"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"authors\\\": \\\"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of the Conference of the European Chapter of the Association for Com...\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"authors\\\": \\\"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"authors\\\": \\\"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2603.11228\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"authors\\\": \\\"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"authors\\\": \\\"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Computational Linguistics\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"authors\\\": \\\"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"authors\\\": \\\"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.09388\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"authors\\\": \\\"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2508.14190\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"authors\\\": \\\"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"authors\\\": \\\"Guti\\\\\\\\'errez, Pedro Antonio and P\\\\\\\\'erez-Ortiz, Mar\\\\\\\\'ia and S\\\\\\\\'anchez-Monedero, Ja...\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"IEEE Transactions on Knowledge and Data Engineering\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of the European Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"authors\\\": \\\"Pang, Bo and Lee, Lillian\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"authors\\\": \\\"Taghipour, Kaveh and Ng, Hwee Tou\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"authors\\\": \\\"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Pattern Analysis and Applications\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"authors\\\": \\\"Chen, Tianqi and Guestrin, Carlos\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"authors\\\": \\\"Lakens, Dani\\\\\\\\\\\\\\\"el\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Social Psychological and Personality Science\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2407.21783\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"authors\\\": \\\"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2310.06825\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"authors\\\": \\\"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\\\", \\\"year\\\": \\\"2008\\\", \\\"venue\\\": \\\"BMC Bioinformatics\\\"}, {\\\"key\\\": \\\"zhu_beat_llms\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\\\", \\\"authors\\\": \\\"Zhu, Biru and Fang, Lifan and Sui, Jiayuan and Lu, Teng\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the 2023 Conference on Empirical Methods in Natural Language Proc...\\\"}, {\\\"key\\\": \\\"dolma\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\\\", \\\"authors\\\": \\\"Soldaini, Luca and Kinney, Rodney and Bhagia, Akshita and Schwenk, Dustin and At...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"fineweb\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"authors\\\": \\\"\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems: Datasets and Benchmarks Track\\\"}, {\\\"key\\\": \\\"mapping_llm_science\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Mapping the Increasing Use of LLMs in Scientific Papers\\\", \\\"authors\\\": \\\"Liang, Weixin and Zhang, Yaohui and Wu, Zhengxuan and Lepp, Haley and Ji, Wenlon...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Language Modeling\\\"}, {\\\"key\\\": \\\"monitoring_ai_review\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\\\", \\\"authors\\\": \\\"Liang, Weixin and Izzo, Zachary and Zhang, Yaohui and Lepp, Haley and Cao, Hanch...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"self_refine\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Refine: Iterative Refinement with Self-Feedback\\\", \\\"authors\\\": \\\"Madaan, Aman and Tandon, Niket and Gupta, Prakhar and Hallinan, Skyler and Gao, ...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"raid\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"authors\\\": \\\"Dugan, Liam and Hwang, Alyssa and Trhl\\\\\\\\'\\\\\\\\ik, Filip and Zhu, Andrew and Ludan, Jo...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 62nd Annual Meeting of the Association for Computational Ling...\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dolma\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fineweb\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mapping_llm_science\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"monitoring_ai_review\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 14, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_refine\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 87, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 89, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 89, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 98, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 98, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 98, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 75, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 89, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"file\\\": \\\"appendix_qlora.tex\\\", \\\"line\\\": 1, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_downstream.tex\\\", \\\"line\\\": 41, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.986, \\\"matched_title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"matched_year\\\": \\\"1989\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=cohen vs api=muller\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"matched_year\\\": \\\"2017\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.344, \\\"matched_title\\\": \\\"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.34 below threshold 0.82\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.253, \\\"matched_title\\\": \\\"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.25 below threshold 0.82\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Defending Against Neural Fake News\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.355, \\\"matched_title\\\": \\\"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.36 below threshold 0.82\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Rewarding Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.871, \\\"matched_title\\\": \\\"QLoRA: Efficient Finetuning of Quantized LLMs\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Scalable watermarking for identifying large language model outputs\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.418, \\\"matched_title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.42 below threshold 0.82\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A survey of modern authorship attribution methods\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Computational methods in authorship attribution\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.497, \\\"matched_title\\\": \\\"The TRIPOD-LLM reporting guideline for studies using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Qwen3 Technical Report\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=team vs api=yang\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.32, \\\"matched_title\\\": \\\"Large AI Models in Health Informatics: Applications, Challenges, and the Future\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.32 below threshold 0.82\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.722, \\\"matched_title\\\": \\\"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.72 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=guti\\\\\\\\'errez vs api=gutiérrez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\\\", \\\"matched_year\\\": \\\"2005\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.298, \\\"matched_title\\\": \\\"XGBoost\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.30 below threshold 0.82\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.976, \\\"matched_title\\\": \\\"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mistral 7B\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Conditional variable importance for random forests\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"zhu_beat_llms\\\", \\\"title\\\": \\\"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beat LLMs at Their Own Game: Zero-Shot LLM-Generated Text Detection via Querying ChatGPT\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dolma\\\", \\\"title\\\": \\\"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Dolma: an Open Corpus of Three Trillion Tokens for Language Model Pretraining Research\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fineweb\\\", \\\"title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The FineWeb Datasets: Decanting the Web for the Finest Text Data at Scale\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mapping_llm_science\\\", \\\"title\\\": \\\"Mapping the Increasing Use of LLMs in Scientific Papers\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mapping the Increasing Use of LLMs in Scientific Papers\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"monitoring_ai_review\\\", \\\"title\\\": \\\"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Monitoring AI-Modified Content at Scale: A Case Study on the Impact of ChatGPT on AI Conference Peer Reviews\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"self_refine\\\", \\\"title\\\": \\\"Self-Refine: Iterative Refinement with Self-Feedback\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Refine: Iterative Refinement with Self-Feedback\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"raid\\\", \\\"title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
      "numLines": 1,
      "startLine": 1,
      "totalLines": 1
    }
  },
  "sourceToolAssistantUUID": "ad043d75-29f3-433b-a350-e03cba2dc94c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 71 · 2026-05-20T02:55:29.724Z_

```json
{
  "parentUuid": "a38f4959-81c1-42e2-a720-cf512fcbb8cd",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "7a99e1e5-a033-46cb-b5d6-7f0d8afcea3d",
  "timestamp": "2026-05-20T02:55:29.724Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 72_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "7a99e1e5-a033-46cb-b5d6-7f0d8afcea3d",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 73_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 74_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: 你是 Reviewer 2，负责审查新颖性、Related Work 覆盖、Framing/写作质量和格式合规。  ## 论文信息 - 标题: \"Depth Fingerprinting: Detecting Recursive Generation Depth in LLM Text Chains\" - 论文路径: /home/ubuntu/.agent-ml-r…",
  "leafUuid": "7a99e1e5-a033-46cb-b5d6-7f0d8afcea3d",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

### Runtime record

_source line 75_

```json
{
  "type": "ai-title",
  "aiTitle": "Review paper on depth fingerprinting for LLM recursive generation",
  "sessionId": "066b279c-ffce-4f4d-ae71-63c4ec55d181"
}
```

---

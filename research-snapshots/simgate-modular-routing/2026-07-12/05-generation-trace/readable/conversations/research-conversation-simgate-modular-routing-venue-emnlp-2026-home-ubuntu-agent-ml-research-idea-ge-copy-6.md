# Research conversation: 项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modul

**Death Avoidance as the Dominant Routing Signal: A Counterfactual Analysis on ScienceWorld (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 73
- **Recorded user turns:** 1
- **Tool calls:** 22
- **Original source:** `logs/chats/exported-trajectories/account-3/7a50ae44-8fc4-4ffa-9059-586963995fe2.jsonl`
- **Structured JSON:** [`abcd0fdce54e75bc50b4.json`](../../sessions/ab/abcd0fdce54e75bc50b4.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-25T15:16:26.664Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-25T15:16:26.664Z",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "content": "项目：simgate-modular-routing\nVenue：emnlp-2026\n论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper\n\nPhase 1 确定性检查结果：\n源码检查: passed=True, 0 critical, 21 warning\n一致性检查: 0 critical, 18 warning\n编译: ✅, 页数: 22\n内部信息: 0 critical, 0 warning\n\n━━━ 用户自定义规则（作为额外检查项）━━━\n## 用户自定义规则（必须遵守）\n### 写作规则\n\n- **[EMNLP 2026]** Limitations 章节只需要写一小段，覆盖 3 个点左右就可以了，不需要写得很长\n- **[EMNLP 2026]** ARR Responsible NLP Checklist在OpenReview的submission form里面（由用户手动填写），而不是在论文pdf里面\n- **[EMNLP 2026]** 一篇文章只能有一个limitations section，放在正文里面，appendix不能有 limitations section\n- **[EMNLP 2026]** abstract 不要超过 200 words\n\n### 审稿规则\n\n- **[EMNLP 2026]** “EMNLP 2026 通过 ARR 统一审稿，Main/Findings 不分开投稿（不是两个Track），Long/Short 也走同一审稿系统，Overall Assessment的评分标准如下：5 = Consider for Award（约前2.5%），4.5 = Borderline Award，4 = Conference（可被主会议接收），3.5 = Borderline Conference，3 = Findings（可被Findings接收），2.5 = Borderline Findings，2 = Resubmit next cycle（需大幅修改，可在下一周期完成），1.5 = Resubmit after next cycle（需大幅修改，无法在下一周期完成），1 = Do not resubmit（需完全重做或与*ACL无关）”\n- **[EMNLP 2026]** EMNLP 2026 restricts long paper submissions to a strict 8-page limit for main text, with unlimited space for references. Mandatory limitations and optional ethical considerations do not count towards this page limit, provided they do not contain excessive additional content.\n\n> 以上规则由用户配置，优先级等同于硬约束。违反会被 Reviewer 标记。\n请将以上规则逐条作为额外审计维度检查。违反的规则用 dimension `[写作规则]` 或 `[审稿规则]` 标记，severity 按实际影响判定。\n\n请按照你的角色指令执行内容结构审计。"
}
```

---

### Runtime record

_source line 2 · 2026-05-25T15:16:26.668Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-25T15:16:26.668Z",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

## Round 1

71 recorded events

### User

_source line 3 · 2026-05-25T15:16:26.710Z_

项目：simgate-modular-routing
Venue：emnlp-2026
论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper

Phase 1 确定性检查结果：
源码检查: passed=True, 0 critical, 21 warning
一致性检查: 0 critical, 18 warning
编译: ✅, 页数: 22
内部信息: 0 critical, 0 warning

━━━ 用户自定义规则（作为额外检查项）━━━
## 用户自定义规则（必须遵守）
### 写作规则

- **[EMNLP 2026]** Limitations 章节只需要写一小段，覆盖 3 个点左右就可以了，不需要写得很长
- **[EMNLP 2026]** ARR Responsible NLP Checklist在OpenReview的submission form里面（由用户手动填写），而不是在论文pdf里面
- **[EMNLP 2026]** 一篇文章只能有一个limitations section，放在正文里面，appendix不能有 limitations section
- **[EMNLP 2026]** abstract 不要超过 200 words

### 审稿规则

- **[EMNLP 2026]** “EMNLP 2026 通过 ARR 统一审稿，Main/Findings 不分开投稿（不是两个Track），Long/Short 也走同一审稿系统，Overall Assessment的评分标准如下：5 = Consider for Award（约前2.5%），4.5 = Borderline Award，4 = Conference（可被主会议接收），3.5 = Borderline Conference，3 = Findings（可被Findings接收），2.5 = Borderline Findings，2 = Resubmit next cycle（需大幅修改，可在下一周期完成），1.5 = Resubmit after next cycle（需大幅修改，无法在下一周期完成），1 = Do not resubmit（需完全重做或与*ACL无关）”
- **[EMNLP 2026]** EMNLP 2026 restricts long paper submissions to a strict 8-page limit for main text, with unlimited space for references. Mandatory limitations and optional ethical considerations do not count towards this page limit, provided they do not contain excessive additional content.

> 以上规则由用户配置，优先级等同于硬约束。违反会被 Reviewer 标记。
请将以上规则逐条作为额外审计维度检查。违反的规则用 dimension `[写作规则]` 或 `[审稿规则]` 标记，severity 按实际影响判定。

请按照你的角色指令执行内容结构审计。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "c078479f-8561-4611-81c7-1126d200d212",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-25T15:16:26.709Z_

```json
{
  "parentUuid": "c078479f-8561-4611-81c7-1126d200d212",
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
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__read_project_file"
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
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__read_project_file"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "9b04bdba-13c4-4cc4-8b1a-d9e065eab220",
  "timestamp": "2026-05-25T15:16:26.709Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-25T15:16:26.709Z_

```json
{
  "parentUuid": "9b04bdba-13c4-4cc4-8b1a-d9e065eab220",
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
  "uuid": "7b66f336-751f-4c15-b7dc-380c5bd693e0",
  "timestamp": "2026-05-25T15:16:26.709Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-25T15:16:26.709Z_

```json
{
  "parentUuid": "7b66f336-751f-4c15-b7dc-380c5bd693e0",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "1c76e28b-3fdb-4914-923d-569dc24908d8",
  "timestamp": "2026-05-25T15:16:26.709Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
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
  "aiTitle": "EMNLP 2026 paper compliance audit for simgate-modular-routing",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Assistant

_source line 8 · 2026-05-25T15:16:31.993Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to perform a content structure audit on a paper. Let me follow the execution flow:

1. Read `skills/global/paper-writing-norms.skill.md` and `skills/global/paper-quality-lessons.skill.md`
2. Read all `.tex` files in the paper directory
3. Audit across all dimensions
4. Output structured findings

Let me start by reading the skill files and finding the tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1c76e28b-3fdb-4914-923d-569dc24908d8",
  "isSidechain": false,
  "requestId": "req_011CbPWRKTdHfLTh78UUqvqC",
  "type": "assistant",
  "uuid": "56ed0626-25d5-4719-8fba-a27594be6d64",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FCPwgvJQc9ViwPP1Pntjsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26881,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26881,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26881,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26881
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

_source line 9 · 2026-05-25T15:16:32.439Z_

开始执行内容结构审计。先读取审计标准和论文源码。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "56ed0626-25d5-4719-8fba-a27594be6d64",
  "isSidechain": false,
  "requestId": "req_011CbPWRKTdHfLTh78UUqvqC",
  "type": "assistant",
  "uuid": "ed4ef50c-e87b-468c-8594-6818ec8f2ad7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FCPwgvJQc9ViwPP1Pntjsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26881,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26881,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26881,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26881
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

_source line 10 · 2026-05-25T15:16:33.559Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SjU9jcLSC9x2YYDBeKgV7R`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ed4ef50c-e87b-468c-8594-6818ec8f2ad7",
  "isSidechain": false,
  "requestId": "req_011CbPWRKTdHfLTh78UUqvqC",
  "type": "assistant",
  "uuid": "8d353d1f-eb76-4cc2-bc6b-5464203311c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FCPwgvJQc9ViwPP1Pntjsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26881,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26881,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26881,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26881
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

_source line 11 · 2026-05-25T15:16:34.346Z_

<details><summary>↩ Tool result · `toolu_01FrRks7rB9JxKs1UXcs6PSK`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "146e7d83-be91-48f0-a1e2-a6a4d880bdd3",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "9ec77204-353e-4087-8eab-6eb38f9edd72",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex"
    ],
    "durationMs": 12,
    "numFiles": 9,
    "truncated": false
  },
  "sourceToolAssistantUUID": "146e7d83-be91-48f0-a1e2-a6a4d880bdd3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-25T15:16:33.581Z_

<details><summary>↩ Tool result · `toolu_01SjU9jcLSC9x2YYDBeKgV7R`</summary>

````text
1	---
2	name: paper-writing-norms
3	description: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。
4	allowed-tools: [Read, Write, Edit, Glob, Grep]
5	scope: global
6	version: 2
7	priority: 9
8	tags:
9	  - writing
10	  - paper
11	  - style
12	  - norms
13	roles:
14	  - agent
15	  - worker
16	  - paper_agent
17	---
18	
19	# 论文写作风格规范
20	
21	> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。
22	
23	---
24	
25	## 一、总体写作哲学
26	
27	### 1.1 故事驱动，不是数据堆砌
28	
29	- 论文必须以"故事线"为核心展开：问题 → 洞察 → 方法 → 验证
30	- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进
31	- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌
32	- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing
33	
34	### 1.2 主线统一性
35	
36	- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**
37	- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C
38	- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机
39	- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线
40	
41	### 1.3 专有名词必须有定义
42	
43	- 首次出现的专有名词/缩写必须给出完整定义和解释
44	- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）
45	- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用
46	- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug
47	
48	### 1.4 写作前必读同类优秀论文
49	
50	- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可
51	- 重点学：
52	  - Abstract 怎么用最少篇幅讲完故事
53	  - Introduction 怎么从大问题切入到具体贡献
54	  - Related Work 怎么 positioning 自己（不是 survey）
55	  - Table/Figure 怎么压缩信息密度
56	- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大
57	- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文
58	
59	---
60	
61	## 二、Abstract 写作规范
62	
63	### 2.1 四个必答问题（150-250 words）
64	
65	Abstract 必须在很短的篇幅内清楚回答：
66	1. **研究什么问题** — 1-2 句话交代背景和痛点
67	2. **为什么重要** — 现有方法的不足（不用写太多）
68	3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）
69	4. **结果说明什么** — 用具体实验结论支撑贡献
70	
71	### 2.2 禁忌
72	
73	- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim
74	- **禁止过度宣传**：不说 "revolutionary"、"groundbreaking"
75	- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元
76	- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了
77	- **缩写必须定义**：Abstract 中首次出现的缩写必须展开
78	
79	### 2.3 审稿人视角检验
80	
81	写完后用这个标准自检：审稿人能否在 30 秒内判断——
82	- 问题是否重要？
83	- 方法是否清楚？
84	- 贡献是否可信？
85	- 结果是否有说服力？
86	
87	---
88	
89	## 三、Introduction 写作规范
90	
91	### 3.1 完整叙事线（5 段结构）
92	
93	Introduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：
94	
95	1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈
96	2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题
97	3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）
98	4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题
99	5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献
100	
101	### 3.2 整体叙事结构
102	
103	```
104	现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结
105	```
106	
107	### 3.3 禁忌
108	
109	- **禁止泛泛介绍**：不要开头就写 "LLMs have shown remarkable capabilities..."，要从具体问题切入
110	- **禁止缺少过渡**：每段之间必须有逻辑连接
111	- **禁止实验报告风格**：Introduction 不是 "我们做了 X 实验得到了 Y 结果" 的罗列
112	- 每条 Contribution 必须有对应的 section/table 支撑
113	- Contribution 列表中不能出现未在前文铺垫过的概念
114	
115	---
116	
117	## 四、Related Work 写作规范
118	
119	### 4.1 目标
120	
121	让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。
122	
123	### 4.2 结构要求
124	
125	- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）
126	- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系
127	- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口
128	
129	### 4.3 禁忌
130	
131	- **禁止论文堆砌**：不要写成 "A proposed X. B proposed Y. C proposed Z." 的列表
132	- **目标不是展示读了多少论文**，而是做归纳和比较
133	- Contribution claim（"To our knowledge, no prior work..."）应放在 Introduction，不在 Related Work
134	
135	### 4.4 引用充足度
136	
137	- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**
138	- 任何一类缺失，审稿人会立刻看出来调研不充分
139	- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足
140	
141	---
142	
143	## 五、去 AI 写作风格（硬规则）
144	
145	以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**
146	
147	### 5.1 严禁破折号（最显著的 AI 痕迹）
148	
149	**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**
150	
151	- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**
152	- 替代方式：用逗号、括号或拆分为两个句子
153	- 强制检查命令：
154	  ```bash
155	  grep -n "—" paper/*.tex     # em-dash，每处人工判断是否必要
156	  grep -n " – " paper/*.tex   # 解释性 en-dash，几乎都应删除
157	  ```
158	- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）
159	
160	### 5.2 段落与句式
161	
162	- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的
163	- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句
164	- **禁止 -ing 短语结尾**：如 "..., highlighting the applicability of..." / "..., demonstrating the effectiveness of..."。这是 AI 写作最典型的标志之一
165	- **禁止连续使用 "Furthermore" / "Moreover" / "Additionally"**：一段内最多用一个过渡词
166	- **避免 "It is worth noting that..." / "Notably, ..."**：直接写要说的内容
167	
168	### 5.3 用词黑名单
169	
170	- 避免 "delve into" / "leverage" / "utilize" / "facilitate" — 用 "explore" / "use" / "enable"
171	- 避免 "a myriad of" / "a plethora of" — 用 "many" / "various"
172	- 避免 "in the realm of" / "in the context of" — 直接说
173	- 避免 "paradigm shift" / "novel" 过度使用
174	
175	### 5.4 校对清单（4 步）
176	
177	1. 全文 proofread 语法和拼写
178	2. 检查所有代词/指示词（this, that, it）是否指代明确
179	3. **`grep "—"` + `grep " – "` 全文清零**（删除所有解释性 dash，§5.1）
180	4. `grep "ing,"` 模式——大部分 -ing 分词短语需要改写
181	
182	---
183	
184	## 六、图表与视觉规范
185	
186	### 6.1 知识密度原则
187	
188	- **图表的信息必须紧凑**——不能为了美观而留大量白空间
189	- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中
190	- 能用 inline text 说清的不要占一整个 Figure
191	
192	### 6.2 表格规范
193	
194	- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）
195	- 小数精度全表统一
196	- 最优加粗、次优下划线
197	- Caption 必须自包含
198	
199	### 6.3 图片规范
200	
201	- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签
202	- 图中字体 >= 7pt（打印后仍可读）
203	- 栏宽约束需匹配目标 venue 模板要求
204	- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页
205	
206	### 6.4 空间效率
207	
208	- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源
209	- 优先使用 `\subfigure` 合并相关图
210	- Table 能 inline 就不要单独浮动
211	- 图表占比与其对叙事的贡献成正比
212	
213	### 6.5 页面节奏
214	
215	好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：
216	
217	- **text-equation-figure 三重奏**：重要概念用"文字解释 → 公式定义 → 图表直觉"三步展开
218	- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏
219	- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float
220	- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）
221	- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）
222	
223	### 6.6 表格 LaTeX 规范
224	
225	**Booktabs 标准（硬规则）**：
226	- 用 `\toprule` / `\midrule` / `\bottomrule`，禁止 `\hline`，禁止竖线 `|`
227	- 用 `\centering` 不用 `\begin{center}`（后者多加垂直空白）
228	- 最优结果加粗（`\textbf{}`），次优下划线（`\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向
229	- 小数精度全表统一（如全部保留 1 位或 2 位）
230	- Caption 在表格上方（`\caption` 在 `\begin{tabular}` 之前）
231	
232	**宽度决策树**：
233	- ≤5 列 → 单栏宽度（`\columnwidth`）
234	- 6–8 列 → 全文宽度（`\textwidth`，双栏模板用 `table*`）
235	- >8 列 → 拆成两张表或移入 appendix
236	
237	---
238	
239	## 七、投稿前通用准备
240	
241	### 7.1 模板必须官方（硬规则）
242	
243	- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）
244	- **不要用**：
245	  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）
246	  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）
247	  - 组里学长留的旧版本（来源不明、无法追溯）
248	- 风险：
249	  - 样式不符合 → desk reject
250	  - margin 不对 → 被审稿人质疑诚信
251	  - reference 格式错 → 被认为不规范
252	- 流程：先查会议官网 templates → 找不到再 `WebSearch "{venue} {year} latex template official"` → 仍找不到汇报 Director（不要用就近年版本顶替）
253	- `\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致
254	
255	### 7.2 投稿要求逐项核对
256	
257	- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A
258	- 页数限制：查目标会议官网
259	- 匿名化要求：review 版 vs camera-ready 版本设置不同
260	- 行号开启（review 版常需）
261	- 字体大小、margin 不得修改 sty 文件
262	
263	### 7.3 最终修改 10 项检查流程
264	
265	提交前必须逐一检查：
266	1. 所有最新实验结果已全部录入
267	2. 根据实验结果将叙事调至最优状态
268	3. 附录所有内容在正文中被引用且融入叙事
269	4. 无数据堆砌（每个数字服务于叙事推进）
270	5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）
271	6. 全文主线统一（idea 变化后各章节逻辑一致）
272	7. 所有专有名词有定义
273	8. 无 AI 风格标志（dash、-ing phrases、过度分段）
274	9. 图表知识密度高、无视觉遮挡
275	10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础
276	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "8d353d1f-eb76-4cc2-bc6b-5464203311c0",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "cf7bc8df-7282-4065-b639-dedf43db2770",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
      "content": "---\nname: paper-writing-norms\ndescription: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 2\npriority: 9\ntags:\n  - writing\n  - paper\n  - style\n  - norms\nroles:\n  - agent\n  - worker\n  - paper_agent\n---\n\n# 论文写作风格规范\n\n> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。\n\n---\n\n## 一、总体写作哲学\n\n### 1.1 故事驱动，不是数据堆砌\n\n- 论文必须以\"故事线\"为核心展开：问题 → 洞察 → 方法 → 验证\n- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进\n- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌\n- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing\n\n### 1.2 主线统一性\n\n- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**\n- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C\n- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机\n- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线\n\n### 1.3 专有名词必须有定义\n\n- 首次出现的专有名词/缩写必须给出完整定义和解释\n- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）\n- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用\n- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug\n\n### 1.4 写作前必读同类优秀论文\n\n- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可\n- 重点学：\n  - Abstract 怎么用最少篇幅讲完故事\n  - Introduction 怎么从大问题切入到具体贡献\n  - Related Work 怎么 positioning 自己（不是 survey）\n  - Table/Figure 怎么压缩信息密度\n- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大\n- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文\n\n---\n\n## 二、Abstract 写作规范\n\n### 2.1 四个必答问题（150-250 words）\n\nAbstract 必须在很短的篇幅内清楚回答：\n1. **研究什么问题** — 1-2 句话交代背景和痛点\n2. **为什么重要** — 现有方法的不足（不用写太多）\n3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）\n4. **结果说明什么** — 用具体实验结论支撑贡献\n\n### 2.2 禁忌\n\n- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim\n- **禁止过度宣传**：不说 \"revolutionary\"、\"groundbreaking\"\n- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元\n- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了\n- **缩写必须定义**：Abstract 中首次出现的缩写必须展开\n\n### 2.3 审稿人视角检验\n\n写完后用这个标准自检：审稿人能否在 30 秒内判断——\n- 问题是否重要？\n- 方法是否清楚？\n- 贡献是否可信？\n- 结果是否有说服力？\n\n---\n\n## 三、Introduction 写作规范\n\n### 3.1 完整叙事线（5 段结构）\n\nIntroduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：\n\n1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈\n2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题\n3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）\n4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题\n5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献\n\n### 3.2 整体叙事结构\n\n```\n现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结\n```\n\n### 3.3 禁忌\n\n- **禁止泛泛介绍**：不要开头就写 \"LLMs have shown remarkable capabilities...\"，要从具体问题切入\n- **禁止缺少过渡**：每段之间必须有逻辑连接\n- **禁止实验报告风格**：Introduction 不是 \"我们做了 X 实验得到了 Y 结果\" 的罗列\n- 每条 Contribution 必须有对应的 section/table 支撑\n- Contribution 列表中不能出现未在前文铺垫过的概念\n\n---\n\n## 四、Related Work 写作规范\n\n### 4.1 目标\n\n让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。\n\n### 4.2 结构要求\n\n- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）\n- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系\n- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口\n\n### 4.3 禁忌\n\n- **禁止论文堆砌**：不要写成 \"A proposed X. B proposed Y. C proposed Z.\" 的列表\n- **目标不是展示读了多少论文**，而是做归纳和比较\n- Contribution claim（\"To our knowledge, no prior work...\"）应放在 Introduction，不在 Related Work\n\n### 4.4 引用充足度\n\n- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**\n- 任何一类缺失，审稿人会立刻看出来调研不充分\n- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足\n\n---\n\n## 五、去 AI 写作风格（硬规则）\n\n以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**\n\n### 5.1 严禁破折号（最显著的 AI 痕迹）\n\n**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**\n\n- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**\n- 替代方式：用逗号、括号或拆分为两个句子\n- 强制检查命令：\n  ```bash\n  grep -n \"—\" paper/*.tex     # em-dash，每处人工判断是否必要\n  grep -n \" – \" paper/*.tex   # 解释性 en-dash，几乎都应删除\n  ```\n- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）\n\n### 5.2 段落与句式\n\n- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的\n- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句\n- **禁止 -ing 短语结尾**：如 \"..., highlighting the applicability of...\" / \"..., demonstrating the effectiveness of...\"。这是 AI 写作最典型的标志之一\n- **禁止连续使用 \"Furthermore\" / \"Moreover\" / \"Additionally\"**：一段内最多用一个过渡词\n- **避免 \"It is worth noting that...\" / \"Notably, ...\"**：直接写要说的内容\n\n### 5.3 用词黑名单\n\n- 避免 \"delve into\" / \"leverage\" / \"utilize\" / \"facilitate\" — 用 \"explore\" / \"use\" / \"enable\"\n- 避免 \"a myriad of\" / \"a plethora of\" — 用 \"many\" / \"various\"\n- 避免 \"in the realm of\" / \"in the context of\" — 直接说\n- 避免 \"paradigm shift\" / \"novel\" 过度使用\n\n### 5.4 校对清单（4 步）\n\n1. 全文 proofread 语法和拼写\n2. 检查所有代词/指示词（this, that, it）是否指代明确\n3. **`grep \"—\"` + `grep \" – \"` 全文清零**（删除所有解释性 dash，§5.1）\n4. `grep \"ing,\"` 模式——大部分 -ing 分词短语需要改写\n\n---\n\n## 六、图表与视觉规范\n\n### 6.1 知识密度原则\n\n- **图表的信息必须紧凑**——不能为了美观而留大量白空间\n- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中\n- 能用 inline text 说清的不要占一整个 Figure\n\n### 6.2 表格规范\n\n- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）\n- 小数精度全表统一\n- 最优加粗、次优下划线\n- Caption 必须自包含\n\n### 6.3 图片规范\n\n- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签\n- 图中字体 >= 7pt（打印后仍可读）\n- 栏宽约束需匹配目标 venue 模板要求\n- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页\n\n### 6.4 空间效率\n\n- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源\n- 优先使用 `\\subfigure` 合并相关图\n- Table 能 inline 就不要单独浮动\n- 图表占比与其对叙事的贡献成正比\n\n### 6.5 页面节奏\n\n好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：\n\n- **text-equation-figure 三重奏**：重要概念用\"文字解释 → 公式定义 → 图表直觉\"三步展开\n- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏\n- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float\n- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）\n- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）\n\n### 6.6 表格 LaTeX 规范\n\n**Booktabs 标准（硬规则）**：\n- 用 `\\toprule` / `\\midrule` / `\\bottomrule`，禁止 `\\hline`，禁止竖线 `|`\n- 用 `\\centering` 不用 `\\begin{center}`（后者多加垂直空白）\n- 最优结果加粗（`\\textbf{}`），次优下划线（`\\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向\n- 小数精度全表统一（如全部保留 1 位或 2 位）\n- Caption 在表格上方（`\\caption` 在 `\\begin{tabular}` 之前）\n\n**宽度决策树**：\n- ≤5 列 → 单栏宽度（`\\columnwidth`）\n- 6–8 列 → 全文宽度（`\\textwidth`，双栏模板用 `table*`）\n- >8 列 → 拆成两张表或移入 appendix\n\n---\n\n## 七、投稿前通用准备\n\n### 7.1 模板必须官方（硬规则）\n\n- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）\n- **不要用**：\n  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）\n  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）\n  - 组里学长留的旧版本（来源不明、无法追溯）\n- 风险：\n  - 样式不符合 → desk reject\n  - margin 不对 → 被审稿人质疑诚信\n  - reference 格式错 → 被认为不规范\n- 流程：先查会议官网 templates → 找不到再 `WebSearch \"{venue} {year} latex template official\"` → 仍找不到汇报 Director（不要用就近年版本顶替）\n- `\\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致\n\n### 7.2 投稿要求逐项核对\n\n- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A\n- 页数限制：查目标会议官网\n- 匿名化要求：review 版 vs camera-ready 版本设置不同\n- 行号开启（review 版常需）\n- 字体大小、margin 不得修改 sty 文件\n\n### 7.3 最终修改 10 项检查流程\n\n提交前必须逐一检查：\n1. 所有最新实验结果已全部录入\n2. 根据实验结果将叙事调至最优状态\n3. 附录所有内容在正文中被引用且融入叙事\n4. 无数据堆砌（每个数字服务于叙事推进）\n5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）\n6. 全文主线统一（idea 变化后各章节逻辑一致）\n7. 所有专有名词有定义\n8. 无 AI 风格标志（dash、-ing phrases、过度分段）\n9. 图表知识密度高、无视觉遮挡\n10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础\n",
      "numLines": 276,
      "startLine": 1,
      "totalLines": 276
    }
  },
  "sourceToolAssistantUUID": "8d353d1f-eb76-4cc2-bc6b-5464203311c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 13 · 2026-05-25T15:16:33.584Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Kjjb44kmDipajod1g49ur1`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-quality-lessons.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cf7bc8df-7282-4065-b639-dedf43db2770",
  "isSidechain": false,
  "requestId": "req_011CbPWRKTdHfLTh78UUqvqC",
  "type": "assistant",
  "uuid": "677f6412-9a32-4534-9a62-b1361696c53e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FCPwgvJQc9ViwPP1Pntjsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26881,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26881,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26881,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26881
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

_source line 14 · 2026-05-25T15:16:33.597Z_

<details><summary>↩ Tool result · `toolu_01Kjjb44kmDipajod1g49ur1`</summary>

````text
1	---
2	name: paper-quality-lessons
3	description: NeurIPS 投稿实战经验总结——人工审查中提炼的写作规范、审查清单、常见反模式。Paper Agent / Reviewer / Director 写论文或审查论文时加载。
4	allowed-tools: [Read, Write, Edit, Glob, Grep]
5	scope: global
6	version: 1
7	tags:
8	  - writing
9	  - paper
10	  - quality
11	  - checklist
12	  - review
13	roles:
14	  - agent
15	  - reviewer
16	  - director
17	  - paper_agent
18	---
19	
20	# 论文写作质量指南（NeurIPS 实战经验）
21	
22	> 来源：2026 年 NeurIPS 投稿期间，从 20+ 项目的人工审查反馈中提炼。
23	> 每条规则都源自真实的 bug / 退回 / 审稿质疑。
24	
25	---
26	
27	## 一、数据诚信与溯源（最高优先级）
28	
29	### 1.1 数字必须有源头
30	
31	- 论文中**每一个数字**必须可追溯到 registry 实验 ID 或原始结果文件
32	- 禁止凭记忆写数字——必须 `cat result.json | head` + `ls -la` 附上文件证据
33	- 计算值（均值、标准差、DID、delta）必须独立重算，不信 Agent 第一手汇报
34	- `paper_provenance.yaml` 覆盖率必须 100%，改数字必须同步更新 provenance
35	
36	> **教训（D149 事件）**：Agent 曾伪造完整的 metrics 数据包括 p-value，事后被 Reviewer 独立 parse JSON 抓出。从此所有关键数据必须 Reviewer 独立验证到字段级别。
37	
38	### 1.2 不同来源数据不能混用
39	
40	- 配对数据必须同 seed、同 c 值、同 N、同 evaluation protocol
41	- 两张表如果 protocol 不同（如 0-shot vs 8-shot），论文必须明确说明
42	- 跨 config 比较 delta 会引入系统误差——必须补跑同 config baseline 后才能比较
43	- 非等量对比必须显式标注（如 "at unmatched volumes"）
44	
45	> **教训（D027 事件）**：不同 config 文件的 baseline 不同，跨 config 比较 delta 值引入了 artifact。
46	
47	### 1.3 结论撤回后不可复活
48	
49	- 被 Director shelved 的数据（如因截断混淆），禁止重新引入论文
50	- `paper_provenance.yaml` 中 `verified: false` 的 claim，不得恢复
51	- 术语修正后不可回退（如 "same norm" → "same per-layer standard deviation"）
52	
53	---
54	
55	## 二、Claim 强度与数据匹配
56	
57	### 2.1 Claim 强度规则
58	
59	| 数据支撑 | 允许的最强表述 |
60	|----------|--------------|
61	| 单 seed, 单数据集 | "preliminary observation", "initial evidence" |
62	| 单 seed, 多数据集 | "suggestive pattern", "indicative trend" |
63	| 多 seed, 单数据集 | 报告均值±标准差，可写 "we find" |
64	| 多 seed, 多数据集 | 可用 "robust", "consistent" |
65	| 统计检验显著 | 可用 "significant", 附 p-value |
66	| 单 seed + 外推到其他条件 | 必须加限定，不能声称 "scale-invariant" 等 |
67	
68	### 2.2 禁止的过强表述
69	
70	- "remarkably stable" → 改为 "relatively stable" 或给出量化波动范围
71	- "confirmed" → 仅 "suggestive" 级别数据不能用
72	- "scale-invariant" → single-seed 验证不够
73	- "We attribute X to Y" → 如果是假说，必须改为 "We hypothesize" + "requiring causal verification"
74	- "roughly twice" → 实际比值必须在 1.8x-2.2x 才能用，否则改为更准确的近似
75	- "domain-agnostic" → 改为 "robust across N domains tested"
76	
77	### 2.3 Claim 降级机制
78	
79	当证据不足以支撑独立 claim 时，应降级为 discussion 中的定性讨论，而非删除。具体做法：
80	- 独立 contribution → Discussion 段落
81	- 硬 claim → 加 caveat 的软 claim
82	- 正文数字 → 移入 Appendix
83	
84	---
85	
86	## 三、叙事与 Storytelling
87	
88	### 3.1 结构原则
89	
90	- 核心 paradox/发现之间必须有**过渡句**桥接，不能让读者在关键处断线
91	- Introduction 每条 Contribution 必须有对应的 section/table 支撑
92	- Discussion 不应重复 Results 的具体数字——引用表格编号
93	- 同一解释不要在多处重复推导——主文写一次 + 指向 Appendix
94	- Limitations 段不要写成一个 17 行大段——拆分为 2-3 个子段按主题分组
95	
96	### 3.2 冷引用（Cold Reference）
97	
98	- 任何首次出现的概念必须有上文铺垫
99	- Introduction 贡献列表中不能突然出现未被提及的模型/方法名
100	
101	### 3.3 不要用旧叙事套新数字
102	
103	新 baseline 出来后若 delta 大幅变化，Section 的叙事逻辑必须重写，不是简单替换数字。
104	
105	### 3.4 Contingency Plan
106	
107	关键实验结果不确定时需预写两套叙事（如 "若结果 A → 叙事 A"、"若结果 B → 叙事 B"），实验完成后选择正确版本。提交前必须确认只留了一套。
108	
109	### 3.5 不要基于中间值做叙事决策
110	
111	70% 进度时的估计往往不够稳定（尤其 GSM8K 等难度分布不均匀的 benchmark），必须等完整数据再定稿叙事。
112	
113	---
114	
115	## 四、术语与一致性
116	
117	### 4.1 术语一致性
118	
119	- 全文必须统一使用正式定义的术语，不得出现同义词漂移
120	- 术语定义后，每次使用必须完全一致（不要有时 "perturbation sensitivity" 有时 "perturbation impact"）
121	
122	### 4.2 统计量一致性
123	
124	- 两个不同的 kappa/p-value 每次出现时必须标注是哪个
125	- 同一个 metric 在不同位置的数字必须完全一致
126	- 修改任何数字后必须全文 grep 确认所有引用处同步
127	
128	### 4.3 p-value 格式
129	
130	- 无前导零、3 位小数：`p = .003`（不是 `p = 0.003`）
131	- 当非劣效性 p<0.001 实际由正向效应驱动时，必须加括注说明
132	
133	### 4.4 例子与定义必须一致
134	
135	Taxonomy 中的定义和对应示例不能自相矛盾。如果定义说 "no new content"，示例中就不能包含新信息。
136	
137	---
138	
139	## 五、投稿前检查清单（Pre-Submission Checklist）
140	
141	### 5.1 占位符扫描（硬门禁）
142	
143	提交前必须 grep 扫描，以下模式要求**零匹配**：
144	```
145	XX.XX, PLACEHOLDER, [If , TODO, TBD, \placeholder{
146	```
147	所有条件占位段落（`[If ...]`）必须替换为最终文本。
148	
149	### 5.2 编译检查
150	
151	- [ ] 编译零 error
152	- [ ] 无 `??` 未解析引用
153	- [ ] 无 > 1pt 的 overfull hbox
154	- [ ] 正文 ≤ 9 页（NeurIPS desk reject 风险）
155	- [ ] 使用当年 style file（`neurips_2026.sty`）
156	- [ ] Review 版启用行号
157	- [ ] 匿名审稿版无作者姓名、无致谢
158	
159	### 5.3 数据完整性
160	
161	- [ ] 论文所有数字与 registry/provenance 交叉验证通过
162	- [ ] 计算值（均值、标准差、DID、delta）独立重算确认
163	- [ ] 所有 evaluation protocol 差异已在论文中说明
164	- [ ] 多 seed 结果报告均值和标准差
165	- [ ] 单 seed 数据在 Limitations 中声明
166	
167	### 5.4 图表检查
168	
169	- [ ] 所有 figure PDF 存在且路径匹配
170	- [ ] 图表不超栏宽（单栏 5.5in / 全宽 6.5in）
171	- [ ] 图中字体 ≥ 7pt
172	- [ ] 小数精度全表统一
173	- [ ] 最优结果加粗、次优下划线
174	- [ ] 表格标题（caption）自包含
175	- [ ] Forest plot 等可视化无 dummy 值（CI_LO=-99 等）
176	
177	### 5.5 引用检查
178	
179	- [ ] 引用覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**（任一缺失说明调研不充分）
180	- [ ] 引用密度与目标会议近年录用论文同量级
181	- [ ] 引用键与 bib 条目 1:1 匹配
182	- [ ] 无孤儿 bib 条目
183	- [ ] 无幻觉引用（所有被引论文实际存在）
184	- [ ] 近年论文的年份/会议准确
185	- [ ] 审稿人要求的引用全部补齐
186	
187	### 5.6 匿名化检查
188	
189	- [ ] 源代码无硬编码绝对路径（`/Users/...`, `/root/...`）
190	- [ ] 配置文件无服务器路径
191	- [ ] Git history 已清理 author 信息（用 fresh repo）
192	- [ ] 项目管理文件不得提交（AGENTS.md, memory.md, registry.yaml, task_context/ 等）
193	- [ ] API Keys 通过环境变量，无泄露
194	
195	### 5.7 会议 Checklist 填写（如目标会议要求）
196	
197	- [ ] Claims: 摘要/Introduction 准确反映实验范围
198	- [ ] Limitations: 正文 Limitations 段 + Appendix 补充
199	- [ ] Experiments: 实验设置完整（exp_id, seed, 超参, 评估 protocol）
200	- [ ] Reproducibility: 数据集公开、代码可用
201	- [ ] Statistical Significance: 多 seed 均值+标准差、置信区间
202	- [ ] Compute: GPU 型号、训练时间、总 GPU-hours
203	- [ ] Licenses: 数据集/模型引用完整
204	- [ ] AI Assistants: 如实声明使用情况
205	- [ ] 每项认真回答（不要全写 N/A）
206	
207	### 5.8 叙事完整性
208	
209	- [ ] Conclusion 包含所有关键限定符（如 "under greedy decoding"）
210	- [ ] Abstract 与正文一致（不能一个写 "single seed" 另一个已是 "10 seeds"）
211	- [ ] 无 Appendix Version A/B 两套叙事残留
212	- [ ] 无 LaTeX 注释与正文混淆
213	- [ ] Contribution claim 在 Introduction 中（不在 Related Work 中）
214	- [ ] 所有专有名词/缩写首次出现时有定义（Abstract 内缩写也必须展开）
215	- [ ] Introduction 与 Method/Results 讲同一条主线（idea 变化后全文逻辑一致）
216	
217	### 5.9 去 AI 风格检查
218	
219	- [ ] **`grep "—" paper/*.tex` 全文清零**（解释性 em-dash 必须全删，最显著的 AI 痕迹）
220	- [ ] **`grep " – " paper/*.tex` 全文清零**（解释性 en-dash 必须全删）
221	- [ ] 无 "-ing," 分词短语结尾（如 "..., demonstrating the effectiveness of..."）
222	- [ ] 无连续 "Furthermore" / "Moreover" / "Additionally"（同段最多 1 个）
223	- [ ] 无 "It is worth noting that..." / "Notably, ..."
224	- [ ] 无 "delve into" / "leverage" / "utilize" / "a myriad of" / "a plethora of"
225	- [ ] 自然段 5-8 句是正常的，不要每 2-3 句就换段
226	
227	### 5.10 模板与同类论文核对
228	
229	- [ ] LaTeX 模板从目标会议官网下载（不是他人转载、不是上一年）
230	- [ ] `\documentclass[]{}` 选项匹配 review / camera-ready 阶段
231	- [ ] 写作前已参考 2-3 篇同领域近 1-2 年优秀论文，叙事节奏对齐
232	
233	---
234	
235	## 六、Reviewer 审查标准
236	
237	### 6.1 CRITICAL 级别（必须修复才能提交）
238	
239	- 论文数字与实验数据不一致
240	- Abstract 与正文矛盾
241	- Evaluation protocol 混淆（如 0-shot 写成 8-shot）
242	- 未经验证的数据写入论文
243	- 占位符残留
244	
245	### 6.2 WARNING 级别（应当修复）
246	
247	- Stale claims（更新了某处数字但忘了同步其他位置）
248	- 过强措辞不匹配数据支撑
249	- 隐式全因子设计误导（如写 "3×3×3=27" 但实际只有 15 格）
250	- 评估指标只描述了部分 domain
251	- 旧版数据引用
252	
253	### 6.3 数据一致性审查流程
254	
255	1. 从 registry 提取所有实验 metrics
256	2. 对照论文中每一个内联数字（到行号级别）
257	3. 独立重算所有衍生值
258	4. 不一致处标注为 CRITICAL
259	5. 近似表述检查实际比值是否在允许范围内
260	
261	---
262	
263	## 七、常见反模式速查表
264	
265	| 反模式 | 症状 | 修复方式 |
266	|--------|------|----------|
267	| Stale claim | 论文某处还引用旧数字 | 改数字后全文 grep 同步 |
268	| Protocol 混淆 | 不同表格用了不同 evaluation 但没说明 | 每张表注明 protocol |
269	| Agent 误报 | 实验结果缺乏文件证据 | 要求 `cat result.json` 截图 |
270	| 混用数据算比值 | 跨 seed/条件/N 的数据混合比较 | 只用严格配对的数据 |
271	| 叙事超越数据 | "confirmed" 但实际只是 suggestive | 匹配 claim 强度到 §2.1 |
272	| 冷引用 | 首次出现的概念无铺垫 | 先建立框架再引入 |
273	| 定义-例子矛盾 | Taxonomy 定义和示例冲突 | 审查所有定义与其示例 |
274	| Placeholder 残留 | XX.XX, TODO, [If...] 未清理 | 提交前 grep 硬门禁 |
275	| Path 泄露 | 代码/config 含服务器绝对路径 | 改为相对路径 |
276	| 重复推导 | 同一解释在 3 处各自推导一遍 | 主文一次 + 引用 Appendix |
277	| Discussion 重复 Results | Discussion 大量复制 Results 数字 | 改为引用表格编号 |
278	| 单 seed overclaim | 单 seed 数据声称 scale-invariant | 加 preliminary/hedging 限定 |
279	| Registry 不同步 | Registry 面值与实际状态不一致 | 以 SSH 实测为准 |
280	| vLLM 静默失败 | max_model_len 太小导致 100% 400 错误 | 预检必须发真实 prompt 验证 |
281	
282	---
283	
284	## 八、写论文前加载的 Skills
285	
286	写论文或做最终审查时，Director/Agent 应按需加载以下 skills：
287	- `latex-paper` — LaTeX 编译与格式
288	- `reference-audit` — 引用真实性审计
289	- `academic-writer` — ML 学术写作规范
290	- `paper-quality-lessons`（本 skill）— 实战经验教训
291	
292	---
293	
294	## 九、附录：投稿经验时间线教训
295	
296	1. **论文数字锁定时机**：最终编译前 24h 锁定所有数字，之后只允许格式修改
297	2. **GPU 不要空闲**：审稿期间如果 Agent 空闲，应该跑 ablation/扩展实验作为 rebuttal 储备
298	3. **匿名化提前做**：不要等到最后一天才检查路径泄露，fresh repo 需要时间清理
299	4. **9 页零余量策略**：NeurIPS 正文 9 页是硬限，每次新增内容必须等量压缩并编译验证
300	5. **Contingency 叙事提前写**：关键实验完成前就写好两版叙事，避免最后一刻仓促改稿
301	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "677f6412-9a32-4534-9a62-b1361696c53e",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "bbd77458-5561-45d6-a6ab-04d7d1d76c1a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-quality-lessons.skill.md",
      "content": "---\nname: paper-quality-lessons\ndescription: NeurIPS 投稿实战经验总结——人工审查中提炼的写作规范、审查清单、常见反模式。Paper Agent / Reviewer / Director 写论文或审查论文时加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 1\ntags:\n  - writing\n  - paper\n  - quality\n  - checklist\n  - review\nroles:\n  - agent\n  - reviewer\n  - director\n  - paper_agent\n---\n\n# 论文写作质量指南（NeurIPS 实战经验）\n\n> 来源：2026 年 NeurIPS 投稿期间，从 20+ 项目的人工审查反馈中提炼。\n> 每条规则都源自真实的 bug / 退回 / 审稿质疑。\n\n---\n\n## 一、数据诚信与溯源（最高优先级）\n\n### 1.1 数字必须有源头\n\n- 论文中**每一个数字**必须可追溯到 registry 实验 ID 或原始结果文件\n- 禁止凭记忆写数字——必须 `cat result.json | head` + `ls -la` 附上文件证据\n- 计算值（均值、标准差、DID、delta）必须独立重算，不信 Agent 第一手汇报\n- `paper_provenance.yaml` 覆盖率必须 100%，改数字必须同步更新 provenance\n\n> **教训（D149 事件）**：Agent 曾伪造完整的 metrics 数据包括 p-value，事后被 Reviewer 独立 parse JSON 抓出。从此所有关键数据必须 Reviewer 独立验证到字段级别。\n\n### 1.2 不同来源数据不能混用\n\n- 配对数据必须同 seed、同 c 值、同 N、同 evaluation protocol\n- 两张表如果 protocol 不同（如 0-shot vs 8-shot），论文必须明确说明\n- 跨 config 比较 delta 会引入系统误差——必须补跑同 config baseline 后才能比较\n- 非等量对比必须显式标注（如 \"at unmatched volumes\"）\n\n> **教训（D027 事件）**：不同 config 文件的 baseline 不同，跨 config 比较 delta 值引入了 artifact。\n\n### 1.3 结论撤回后不可复活\n\n- 被 Director shelved 的数据（如因截断混淆），禁止重新引入论文\n- `paper_provenance.yaml` 中 `verified: false` 的 claim，不得恢复\n- 术语修正后不可回退（如 \"same norm\" → \"same per-layer standard deviation\"）\n\n---\n\n## 二、Claim 强度与数据匹配\n\n### 2.1 Claim 强度规则\n\n| 数据支撑 | 允许的最强表述 |\n|----------|--------------|\n| 单 seed, 单数据集 | \"preliminary observation\", \"initial evidence\" |\n| 单 seed, 多数据集 | \"suggestive pattern\", \"indicative trend\" |\n| 多 seed, 单数据集 | 报告均值±标准差，可写 \"we find\" |\n| 多 seed, 多数据集 | 可用 \"robust\", \"consistent\" |\n| 统计检验显著 | 可用 \"significant\", 附 p-value |\n| 单 seed + 外推到其他条件 | 必须加限定，不能声称 \"scale-invariant\" 等 |\n\n### 2.2 禁止的过强表述\n\n- \"remarkably stable\" → 改为 \"relatively stable\" 或给出量化波动范围\n- \"confirmed\" → 仅 \"suggestive\" 级别数据不能用\n- \"scale-invariant\" → single-seed 验证不够\n- \"We attribute X to Y\" → 如果是假说，必须改为 \"We hypothesize\" + \"requiring causal verification\"\n- \"roughly twice\" → 实际比值必须在 1.8x-2.2x 才能用，否则改为更准确的近似\n- \"domain-agnostic\" → 改为 \"robust across N domains tested\"\n\n### 2.3 Claim 降级机制\n\n当证据不足以支撑独立 claim 时，应降级为 discussion 中的定性讨论，而非删除。具体做法：\n- 独立 contribution → Discussion 段落\n- 硬 claim → 加 caveat 的软 claim\n- 正文数字 → 移入 Appendix\n\n---\n\n## 三、叙事与 Storytelling\n\n### 3.1 结构原则\n\n- 核心 paradox/发现之间必须有**过渡句**桥接，不能让读者在关键处断线\n- Introduction 每条 Contribution 必须有对应的 section/table 支撑\n- Discussion 不应重复 Results 的具体数字——引用表格编号\n- 同一解释不要在多处重复推导——主文写一次 + 指向 Appendix\n- Limitations 段不要写成一个 17 行大段——拆分为 2-3 个子段按主题分组\n\n### 3.2 冷引用（Cold Reference）\n\n- 任何首次出现的概念必须有上文铺垫\n- Introduction 贡献列表中不能突然出现未被提及的模型/方法名\n\n### 3.3 不要用旧叙事套新数字\n\n新 baseline 出来后若 delta 大幅变化，Section 的叙事逻辑必须重写，不是简单替换数字。\n\n### 3.4 Contingency Plan\n\n关键实验结果不确定时需预写两套叙事（如 \"若结果 A → 叙事 A\"、\"若结果 B → 叙事 B\"），实验完成后选择正确版本。提交前必须确认只留了一套。\n\n### 3.5 不要基于中间值做叙事决策\n\n70% 进度时的估计往往不够稳定（尤其 GSM8K 等难度分布不均匀的 benchmark），必须等完整数据再定稿叙事。\n\n---\n\n## 四、术语与一致性\n\n### 4.1 术语一致性\n\n- 全文必须统一使用正式定义的术语，不得出现同义词漂移\n- 术语定义后，每次使用必须完全一致（不要有时 \"perturbation sensitivity\" 有时 \"perturbation impact\"）\n\n### 4.2 统计量一致性\n\n- 两个不同的 kappa/p-value 每次出现时必须标注是哪个\n- 同一个 metric 在不同位置的数字必须完全一致\n- 修改任何数字后必须全文 grep 确认所有引用处同步\n\n### 4.3 p-value 格式\n\n- 无前导零、3 位小数：`p = .003`（不是 `p = 0.003`）\n- 当非劣效性 p<0.001 实际由正向效应驱动时，必须加括注说明\n\n### 4.4 例子与定义必须一致\n\nTaxonomy 中的定义和对应示例不能自相矛盾。如果定义说 \"no new content\"，示例中就不能包含新信息。\n\n---\n\n## 五、投稿前检查清单（Pre-Submission Checklist）\n\n### 5.1 占位符扫描（硬门禁）\n\n提交前必须 grep 扫描，以下模式要求**零匹配**：\n```\nXX.XX, PLACEHOLDER, [If , TODO, TBD, \\placeholder{\n```\n所有条件占位段落（`[If ...]`）必须替换为最终文本。\n\n### 5.2 编译检查\n\n- [ ] 编译零 error\n- [ ] 无 `??` 未解析引用\n- [ ] 无 > 1pt 的 overfull hbox\n- [ ] 正文 ≤ 9 页（NeurIPS desk reject 风险）\n- [ ] 使用当年 style file（`neurips_2026.sty`）\n- [ ] Review 版启用行号\n- [ ] 匿名审稿版无作者姓名、无致谢\n\n### 5.3 数据完整性\n\n- [ ] 论文所有数字与 registry/provenance 交叉验证通过\n- [ ] 计算值（均值、标准差、DID、delta）独立重算确认\n- [ ] 所有 evaluation protocol 差异已在论文中说明\n- [ ] 多 seed 结果报告均值和标准差\n- [ ] 单 seed 数据在 Limitations 中声明\n\n### 5.4 图表检查\n\n- [ ] 所有 figure PDF 存在且路径匹配\n- [ ] 图表不超栏宽（单栏 5.5in / 全宽 6.5in）\n- [ ] 图中字体 ≥ 7pt\n- [ ] 小数精度全表统一\n- [ ] 最优结果加粗、次优下划线\n- [ ] 表格标题（caption）自包含\n- [ ] Forest plot 等可视化无 dummy 值（CI_LO=-99 等）\n\n### 5.5 引用检查\n\n- [ ] 引用覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**（任一缺失说明调研不充分）\n- [ ] 引用密度与目标会议近年录用论文同量级\n- [ ] 引用键与 bib 条目 1:1 匹配\n- [ ] 无孤儿 bib 条目\n- [ ] 无幻觉引用（所有被引论文实际存在）\n- [ ] 近年论文的年份/会议准确\n- [ ] 审稿人要求的引用全部补齐\n\n### 5.6 匿名化检查\n\n- [ ] 源代码无硬编码绝对路径（`/Users/...`, `/root/...`）\n- [ ] 配置文件无服务器路径\n- [ ] Git history 已清理 author 信息（用 fresh repo）\n- [ ] 项目管理文件不得提交（AGENTS.md, memory.md, registry.yaml, task_context/ 等）\n- [ ] API Keys 通过环境变量，无泄露\n\n### 5.7 会议 Checklist 填写（如目标会议要求）\n\n- [ ] Claims: 摘要/Introduction 准确反映实验范围\n- [ ] Limitations: 正文 Limitations 段 + Appendix 补充\n- [ ] Experiments: 实验设置完整（exp_id, seed, 超参, 评估 protocol）\n- [ ] Reproducibility: 数据集公开、代码可用\n- [ ] Statistical Significance: 多 seed 均值+标准差、置信区间\n- [ ] Compute: GPU 型号、训练时间、总 GPU-hours\n- [ ] Licenses: 数据集/模型引用完整\n- [ ] AI Assistants: 如实声明使用情况\n- [ ] 每项认真回答（不要全写 N/A）\n\n### 5.8 叙事完整性\n\n- [ ] Conclusion 包含所有关键限定符（如 \"under greedy decoding\"）\n- [ ] Abstract 与正文一致（不能一个写 \"single seed\" 另一个已是 \"10 seeds\"）\n- [ ] 无 Appendix Version A/B 两套叙事残留\n- [ ] 无 LaTeX 注释与正文混淆\n- [ ] Contribution claim 在 Introduction 中（不在 Related Work 中）\n- [ ] 所有专有名词/缩写首次出现时有定义（Abstract 内缩写也必须展开）\n- [ ] Introduction 与 Method/Results 讲同一条主线（idea 变化后全文逻辑一致）\n\n### 5.9 去 AI 风格检查\n\n- [ ] **`grep \"—\" paper/*.tex` 全文清零**（解释性 em-dash 必须全删，最显著的 AI 痕迹）\n- [ ] **`grep \" – \" paper/*.tex` 全文清零**（解释性 en-dash 必须全删）\n- [ ] 无 \"-ing,\" 分词短语结尾（如 \"..., demonstrating the effectiveness of...\"）\n- [ ] 无连续 \"Furthermore\" / \"Moreover\" / \"Additionally\"（同段最多 1 个）\n- [ ] 无 \"It is worth noting that...\" / \"Notably, ...\"\n- [ ] 无 \"delve into\" / \"leverage\" / \"utilize\" / \"a myriad of\" / \"a plethora of\"\n- [ ] 自然段 5-8 句是正常的，不要每 2-3 句就换段\n\n### 5.10 模板与同类论文核对\n\n- [ ] LaTeX 模板从目标会议官网下载（不是他人转载、不是上一年）\n- [ ] `\\documentclass[]{}` 选项匹配 review / camera-ready 阶段\n- [ ] 写作前已参考 2-3 篇同领域近 1-2 年优秀论文，叙事节奏对齐\n\n---\n\n## 六、Reviewer 审查标准\n\n### 6.1 CRITICAL 级别（必须修复才能提交）\n\n- 论文数字与实验数据不一致\n- Abstract 与正文矛盾\n- Evaluation protocol 混淆（如 0-shot 写成 8-shot）\n- 未经验证的数据写入论文\n- 占位符残留\n\n### 6.2 WARNING 级别（应当修复）\n\n- Stale claims（更新了某处数字但忘了同步其他位置）\n- 过强措辞不匹配数据支撑\n- 隐式全因子设计误导（如写 \"3×3×3=27\" 但实际只有 15 格）\n- 评估指标只描述了部分 domain\n- 旧版数据引用\n\n### 6.3 数据一致性审查流程\n\n1. 从 registry 提取所有实验 metrics\n2. 对照论文中每一个内联数字（到行号级别）\n3. 独立重算所有衍生值\n4. 不一致处标注为 CRITICAL\n5. 近似表述检查实际比值是否在允许范围内\n\n---\n\n## 七、常见反模式速查表\n\n| 反模式 | 症状 | 修复方式 |\n|--------|------|----------|\n| Stale claim | 论文某处还引用旧数字 | 改数字后全文 grep 同步 |\n| Protocol 混淆 | 不同表格用了不同 evaluation 但没说明 | 每张表注明 protocol |\n| Agent 误报 | 实验结果缺乏文件证据 | 要求 `cat result.json` 截图 |\n| 混用数据算比值 | 跨 seed/条件/N 的数据混合比较 | 只用严格配对的数据 |\n| 叙事超越数据 | \"confirmed\" 但实际只是 suggestive | 匹配 claim 强度到 §2.1 |\n| 冷引用 | 首次出现的概念无铺垫 | 先建立框架再引入 |\n| 定义-例子矛盾 | Taxonomy 定义和示例冲突 | 审查所有定义与其示例 |\n| Placeholder 残留 | XX.XX, TODO, [If...] 未清理 | 提交前 grep 硬门禁 |\n| Path 泄露 | 代码/config 含服务器绝对路径 | 改为相对路径 |\n| 重复推导 | 同一解释在 3 处各自推导一遍 | 主文一次 + 引用 Appendix |\n| Discussion 重复 Results | Discussion 大量复制 Results 数字 | 改为引用表格编号 |\n| 单 seed overclaim | 单 seed 数据声称 scale-invariant | 加 preliminary/hedging 限定 |\n| Registry 不同步 | Registry 面值与实际状态不一致 | 以 SSH 实测为准 |\n| vLLM 静默失败 | max_model_len 太小导致 100% 400 错误 | 预检必须发真实 prompt 验证 |\n\n---\n\n## 八、写论文前加载的 Skills\n\n写论文或做最终审查时，Director/Agent 应按需加载以下 skills：\n- `latex-paper` — LaTeX 编译与格式\n- `reference-audit` — 引用真实性审计\n- `academic-writer` — ML 学术写作规范\n- `paper-quality-lessons`（本 skill）— 实战经验教训\n\n---\n\n## 九、附录：投稿经验时间线教训\n\n1. **论文数字锁定时机**：最终编译前 24h 锁定所有数字，之后只允许格式修改\n2. **GPU 不要空闲**：审稿期间如果 Agent 空闲，应该跑 ablation/扩展实验作为 rebuttal 储备\n3. **匿名化提前做**：不要等到最后一天才检查路径泄露，fresh repo 需要时间清理\n4. **9 页零余量策略**：NeurIPS 正文 9 页是硬限，每次新增内容必须等量压缩并编译验证\n5. **Contingency 叙事提前写**：关键实验完成前就写好两版叙事，避免最后一刻仓促改稿\n",
      "numLines": 301,
      "startLine": 1,
      "totalLines": 301
    }
  },
  "sourceToolAssistantUUID": "677f6412-9a32-4534-9a62-b1361696c53e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 15 · 2026-05-25T15:16:34.329Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01FrRks7rB9JxKs1UXcs6PSK`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bbd77458-5561-45d6-a6ab-04d7d1d76c1a",
  "isSidechain": false,
  "requestId": "req_011CbPWRKTdHfLTh78UUqvqC",
  "type": "assistant",
  "uuid": "146e7d83-be91-48f0-a1e2-a6a4d880bdd3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FCPwgvJQc9ViwPP1Pntjsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26881,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26881,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26881,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26881
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

_source line 16_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 21 warnin…",
  "leafUuid": "9ec77204-353e-4087-8eab-6eb38f9edd72",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit for simgate-modular-routing",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Assistant

_source line 18 · 2026-05-25T15:16:37.759Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read all the .tex files. Let me read them all in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9ec77204-353e-4087-8eab-6eb38f9edd72",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "c90ac1f4-be46-4ba4-bbbf-da75c5355ff1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 19 · 2026-05-25T15:16:37.760Z_

读取所有 .tex 源文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c90ac1f4-be46-4ba4-bbbf-da75c5355ff1",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "602aa5a3-cfc8-4c74-9d45-885413f6a6d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 20 · 2026-05-25T15:16:38.258Z_

<details open><summary>🔧 Tool call — Read · `toolu_01F7Rr4WC56iXZakatHozkcb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "602aa5a3-cfc8-4c74-9d45-885413f6a6d2",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "915a1093-36f9-4fc5-aaab-642a9ab0d303",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 21 · 2026-05-25T15:16:42.583Z_

<details><summary>↩ Tool result · `toolu_019gTtSHXnspfo7kNkbFKohx`</summary>

```text
1	% Responsible NLP Research Checklist
2	% Required as appendix for ARR/EMNLP 2026 submissions
3	
4	\section*{Responsible NLP Research Checklist}
5	
6	This paper presents a diagnostic framework for analyzing routing signal in modular LLM agents, applied to ScienceWorld, MATH, and ALFWorld environments.
7	
8	\subsection*{A \quad For Every Submission}
9	
10	\begin{enumerate}
11	\item[\textbf{A1.}] \textbf{Did you describe the limitations of your work?}\\
12	Yes. A dedicated \textbf{Limitations} section (after Section~6) discusses environmental scope (single primary environment, one backbone), methodological constraints (single-pass ReAct baseline, episode-level labels), and statistical limitations (cluster bootstrap with $K{=}11$).
13	
14	\item[\textbf{A2.}] \textbf{Did you discuss any potential risks of your work?}\\
15	Yes. The \textbf{Ethics Statement} (after Limitations) confirms no human subjects or private data are involved, all models are publicly available, and computational costs are reported.
16	\end{enumerate}
17	
18	\subsection*{B \quad Did you use or create scientific artifacts?}
19	
20	Yes. We use existing environments (ScienceWorld, ALFWorld, MATH) and language models (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Qwen2.5-72B-Instruct, Gemma-2-9B-it, Qwen3-0.6B/1.7B/4B).
21	
22	\begin{enumerate}
23	\item[\textbf{B1.}] \textbf{Did you cite the creators of artifacts you used?}\\
24	Yes. All environments, models, and methods are cited: ScienceWorld~\cite{scienceworld-2022}, ALFWorld~\cite{alfworld-2021}, MATH~\cite{math-2021}, Qwen2.5~\cite{qwen25-2024}, Llama-3.1~\cite{llama3-2024}, ReAct~\cite{react-2023}, Reflexion~\cite{reflexion-2023}.
25	
26	\item[\textbf{B2.}] \textbf{Did you discuss the license or terms for use and/or distribution of any artifacts?}\\
27	Yes. The Ethics Statement states that all evaluation environments (ScienceWorld, ALFWorld, MATH) are released under permissive open-source licenses (Apache 2.0 / MIT) and all models are publicly available for research use.
28	
29	\item[\textbf{B3.}] \textbf{Did you discuss if your use of existing artifact(s) was consistent with their intended use?}\\
30	Yes. We use ScienceWorld, ALFWorld, and MATH as evaluation environments for language model agents, consistent with their intended purpose as agent benchmarks.
31	
32	\item[\textbf{B4.}] \textbf{Did you discuss the steps taken to check whether the data contains any information that names or uniquely identifies individual people or offensive content?}\\
33	Not applicable. All data is generated from simulation environments (ScienceWorld, ALFWorld) or mathematical problems (MATH). No human-generated text, personal information, or user data is involved.
34	
35	\item[\textbf{B5.}] \textbf{Did you provide documentation of the artifacts?}\\
36	Yes. Section~\ref{sec:method} and Appendix~\ref{app:per-task} describe the environments, task types, and data collection procedures. Appendix~\ref{app:router-details} documents router training configurations.
37	
38	\item[\textbf{B6.}] \textbf{Did you report relevant statistics like the number of examples, details of train/test/dev splits, etc.?}\\
39	Yes. We report: 245 episodes across 11 task types (Table~\ref{tab:per-task}), 795 MATH problems (Section~\ref{sec:cross-env}), 135 ALFWorld games (Section~\ref{sec:cross-env}), per-task episode counts (Table~\ref{tab:per-task}), and router training splits with cross-validation details (Appendix~\ref{app:router-details}).
40	\end{enumerate}
41	
42	\subsection*{C \quad Did you run computational experiments?}
43	
44	Yes.
45	
46	\begin{enumerate}
47	\item[\textbf{C1.}] \textbf{Did you report the number of parameters in the models used, the total computational budget, and computing infrastructure used?}\\
48	Yes. Model sizes are specified (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Qwen2.5-72B-Instruct, Gemma-2-9B-it, Qwen3-0.6B/1.7B/4B). The Ethics Statement reports 2$\times$ NVIDIA RTX 5090 (32GB) and 4$\times$ NVIDIA RTX 6000 PRO (96GB), totaling approximately 200 GPU-hours with an estimated carbon footprint of approximately 25\,kg CO$_2$eq.
49	
50	\item[\textbf{C2.}] \textbf{Did you discuss the experimental setup, including hyperparameter search and best-found hyperparameter values?}\\
51	Yes. Table~\ref{tab:hyperparams} (Appendix~\ref{app:router-details}) provides complete hyperparameters for both router architectures. Section~\ref{sec:router-diagnostic} and Appendix~\ref{app:router-details} describe the evaluation methodology. Gradient accumulation selection is justified in Appendix~\ref{app:router-details}.
52	
53	\item[\textbf{C3.}] \textbf{Did you report descriptive statistics about your results with at least a measure of central tendency and variation?}\\
54	Yes. We report mean$\pm$std for router accuracy across seeds (Section~\ref{sec:router-diagnostic}), bootstrap 95\% CIs for DAF and correlation metrics (Section~\ref{sec:death-decomp}), and per-seed breakdowns (Appendix~\ref{app:seed-robustness}). All counterfactual diagnostic experiments use a fixed seed (42) with variability captured through 20 episode variations per task type; router training experiments (Section~\ref{sec:router-diagnostic}) use 4 seeds per configuration.
55	
56	\item[\textbf{C4.}] \textbf{If you used existing packages, did you report the implementation, model, and parameter settings used?}\\
57	Yes. We specify vLLM for inference, LoRA for fine-tuning, and provide all relevant configuration parameters (Table~\ref{tab:hyperparams}). Model identifiers are given precisely (e.g., Qwen2.5-7B-Instruct, Qwen3-1.7B).
58	\end{enumerate}
59	
60	\subsection*{D \quad Did you use human annotators or participants?}
61	
62	No. All labels are generated automatically via the counterfactual labeling algorithm (Algorithm~1). No human annotation or participation is involved.
63	
64	\begin{enumerate}
65	\item[\textbf{D1.}] Not applicable.
66	\item[\textbf{D2.}] Not applicable.
67	\item[\textbf{D3.}] Not applicable.
68	\item[\textbf{D4.}] Not applicable.
69	\item[\textbf{D5.}] Not applicable.
70	\end{enumerate}
71	
72	\subsection*{E \quad Did you use AI assistants?}
73	
74	\begin{enumerate}
75	\item[\textbf{E1.}] \textbf{Did you include information about your use of AI assistants?}\\
76	Yes. Claude (Anthropic) was used for code development, data analysis scripting, and manuscript drafting. All experimental design, scientific claims, and interpretation of results were conducted by the authors.
77	\end{enumerate}
78	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2d816c0b-f58e-4b11-8466-f64d6679f6dd",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "d710b15e-4479-4d7a-83a3-889e7d70420a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex",
      "content": "% Responsible NLP Research Checklist\n% Required as appendix for ARR/EMNLP 2026 submissions\n\n\\section*{Responsible NLP Research Checklist}\n\nThis paper presents a diagnostic framework for analyzing routing signal in modular LLM agents, applied to ScienceWorld, MATH, and ALFWorld environments.\n\n\\subsection*{A \\quad For Every Submission}\n\n\\begin{enumerate}\n\\item[\\textbf{A1.}] \\textbf{Did you describe the limitations of your work?}\\\\\nYes. A dedicated \\textbf{Limitations} section (after Section~6) discusses environmental scope (single primary environment, one backbone), methodological constraints (single-pass ReAct baseline, episode-level labels), and statistical limitations (cluster bootstrap with $K{=}11$).\n\n\\item[\\textbf{A2.}] \\textbf{Did you discuss any potential risks of your work?}\\\\\nYes. The \\textbf{Ethics Statement} (after Limitations) confirms no human subjects or private data are involved, all models are publicly available, and computational costs are reported.\n\\end{enumerate}\n\n\\subsection*{B \\quad Did you use or create scientific artifacts?}\n\nYes. We use existing environments (ScienceWorld, ALFWorld, MATH) and language models (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Qwen2.5-72B-Instruct, Gemma-2-9B-it, Qwen3-0.6B/1.7B/4B).\n\n\\begin{enumerate}\n\\item[\\textbf{B1.}] \\textbf{Did you cite the creators of artifacts you used?}\\\\\nYes. All environments, models, and methods are cited: ScienceWorld~\\cite{scienceworld-2022}, ALFWorld~\\cite{alfworld-2021}, MATH~\\cite{math-2021}, Qwen2.5~\\cite{qwen25-2024}, Llama-3.1~\\cite{llama3-2024}, ReAct~\\cite{react-2023}, Reflexion~\\cite{reflexion-2023}.\n\n\\item[\\textbf{B2.}] \\textbf{Did you discuss the license or terms for use and/or distribution of any artifacts?}\\\\\nYes. The Ethics Statement states that all evaluation environments (ScienceWorld, ALFWorld, MATH) are released under permissive open-source licenses (Apache 2.0 / MIT) and all models are publicly available for research use.\n\n\\item[\\textbf{B3.}] \\textbf{Did you discuss if your use of existing artifact(s) was consistent with their intended use?}\\\\\nYes. We use ScienceWorld, ALFWorld, and MATH as evaluation environments for language model agents, consistent with their intended purpose as agent benchmarks.\n\n\\item[\\textbf{B4.}] \\textbf{Did you discuss the steps taken to check whether the data contains any information that names or uniquely identifies individual people or offensive content?}\\\\\nNot applicable. All data is generated from simulation environments (ScienceWorld, ALFWorld) or mathematical problems (MATH). No human-generated text, personal information, or user data is involved.\n\n\\item[\\textbf{B5.}] \\textbf{Did you provide documentation of the artifacts?}\\\\\nYes. Section~\\ref{sec:method} and Appendix~\\ref{app:per-task} describe the environments, task types, and data collection procedures. Appendix~\\ref{app:router-details} documents router training configurations.\n\n\\item[\\textbf{B6.}] \\textbf{Did you report relevant statistics like the number of examples, details of train/test/dev splits, etc.?}\\\\\nYes. We report: 245 episodes across 11 task types (Table~\\ref{tab:per-task}), 795 MATH problems (Section~\\ref{sec:cross-env}), 135 ALFWorld games (Section~\\ref{sec:cross-env}), per-task episode counts (Table~\\ref{tab:per-task}), and router training splits with cross-validation details (Appendix~\\ref{app:router-details}).\n\\end{enumerate}\n\n\\subsection*{C \\quad Did you run computational experiments?}\n\nYes.\n\n\\begin{enumerate}\n\\item[\\textbf{C1.}] \\textbf{Did you report the number of parameters in the models used, the total computational budget, and computing infrastructure used?}\\\\\nYes. Model sizes are specified (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Qwen2.5-72B-Instruct, Gemma-2-9B-it, Qwen3-0.6B/1.7B/4B). The Ethics Statement reports 2$\\times$ NVIDIA RTX 5090 (32GB) and 4$\\times$ NVIDIA RTX 6000 PRO (96GB), totaling approximately 200 GPU-hours with an estimated carbon footprint of approximately 25\\,kg CO$_2$eq.\n\n\\item[\\textbf{C2.}] \\textbf{Did you discuss the experimental setup, including hyperparameter search and best-found hyperparameter values?}\\\\\nYes. Table~\\ref{tab:hyperparams} (Appendix~\\ref{app:router-details}) provides complete hyperparameters for both router architectures. Section~\\ref{sec:router-diagnostic} and Appendix~\\ref{app:router-details} describe the evaluation methodology. Gradient accumulation selection is justified in Appendix~\\ref{app:router-details}.\n\n\\item[\\textbf{C3.}] \\textbf{Did you report descriptive statistics about your results with at least a measure of central tendency and variation?}\\\\\nYes. We report mean$\\pm$std for router accuracy across seeds (Section~\\ref{sec:router-diagnostic}), bootstrap 95\\% CIs for DAF and correlation metrics (Section~\\ref{sec:death-decomp}), and per-seed breakdowns (Appendix~\\ref{app:seed-robustness}). All counterfactual diagnostic experiments use a fixed seed (42) with variability captured through 20 episode variations per task type; router training experiments (Section~\\ref{sec:router-diagnostic}) use 4 seeds per configuration.\n\n\\item[\\textbf{C4.}] \\textbf{If you used existing packages, did you report the implementation, model, and parameter settings used?}\\\\\nYes. We specify vLLM for inference, LoRA for fine-tuning, and provide all relevant configuration parameters (Table~\\ref{tab:hyperparams}). Model identifiers are given precisely (e.g., Qwen2.5-7B-Instruct, Qwen3-1.7B).\n\\end{enumerate}\n\n\\subsection*{D \\quad Did you use human annotators or participants?}\n\nNo. All labels are generated automatically via the counterfactual labeling algorithm (Algorithm~1). No human annotation or participation is involved.\n\n\\begin{enumerate}\n\\item[\\textbf{D1.}] Not applicable.\n\\item[\\textbf{D2.}] Not applicable.\n\\item[\\textbf{D3.}] Not applicable.\n\\item[\\textbf{D4.}] Not applicable.\n\\item[\\textbf{D5.}] Not applicable.\n\\end{enumerate}\n\n\\subsection*{E \\quad Did you use AI assistants?}\n\n\\begin{enumerate}\n\\item[\\textbf{E1.}] \\textbf{Did you include information about your use of AI assistants?}\\\\\nYes. Claude (Anthropic) was used for code development, data analysis scripting, and manuscript drafting. All experimental design, scientific claims, and interpretation of results were conducted by the authors.\n\\end{enumerate}\n",
      "numLines": 78,
      "startLine": 1,
      "totalLines": 78
    }
  },
  "sourceToolAssistantUUID": "2d816c0b-f58e-4b11-8466-f64d6679f6dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-25T15:16:38.263Z_

<details><summary>↩ Tool result · `toolu_01F7Rr4WC56iXZakatHozkcb`</summary>

```text
1	\begin{abstract}
2	LLM agent routing---deciding when to rely on internal reasoning versus external computation---is typically addressed by training routers directly, without first diagnosing what signal drives the routing preference. We introduce an episode-level counterfactual framework that decomposes routing signal into mechanistic components by comparing pure-strategy outcomes \emph{before} any router is built. Applied to ScienceWorld, the framework reveals that 78.9\% of non-tie routing labels arise from a single mechanism: \emph{death asymmetry}, where internal reasoning triggers catastrophic failure while the deterministic strategy survives. This pattern replicates across three model families spanning 7B to 70B parameters; at larger scale, death avoidance accounts for the entire performance gap between strategies. Always-deterministic matches 96.3\% of oracle routing decisions, leaving negligible room for learned step-level routing. Boundary probes on MATH and ALFWorld confirm the framework distinguishes qualitatively different routing mechanisms---including environments where no routing signal exists\footnote{Code and data are available at \url{https://anonymous.4open.science/r/simgate-modular-routing-ED12/}.}.
3	\end{abstract}
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "915a1093-36f9-4fc5-aaab-642a9ab0d303",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "f6f3d377-cc1c-460b-8e53-0f2acd1aebd0",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nLLM agent routing---deciding when to rely on internal reasoning versus external computation---is typically addressed by training routers directly, without first diagnosing what signal drives the routing preference. We introduce an episode-level counterfactual framework that decomposes routing signal into mechanistic components by comparing pure-strategy outcomes \\emph{before} any router is built. Applied to ScienceWorld, the framework reveals that 78.9\\% of non-tie routing labels arise from a single mechanism: \\emph{death asymmetry}, where internal reasoning triggers catastrophic failure while the deterministic strategy survives. This pattern replicates across three model families spanning 7B to 70B parameters; at larger scale, death avoidance accounts for the entire performance gap between strategies. Always-deterministic matches 96.3\\% of oracle routing decisions, leaving negligible room for learned step-level routing. Boundary probes on MATH and ALFWorld confirm the framework distinguishes qualitatively different routing mechanisms---including environments where no routing signal exists\\footnote{Code and data are available at \\url{https://anonymous.4open.science/r/simgate-modular-routing-ED12/}.}.\n\\end{abstract}\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  },
  "sourceToolAssistantUUID": "915a1093-36f9-4fc5-aaab-642a9ab0d303",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-25T15:16:39.167Z_

<details open><summary>🔧 Tool call — Read · `toolu_01W5ZWtQ65Hx3GGPQ7UoYMU7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f6f3d377-cc1c-460b-8e53-0f2acd1aebd0",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "b19c5d9c-8379-4351-963d-606400b0dd42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 24 · 2026-05-25T15:16:39.172Z_

<details><summary>↩ Tool result · `toolu_01W5ZWtQ65Hx3GGPQ7UoYMU7`</summary>

```text
1	\section{Introduction}
2	
3	\begin{figure*}[t]
4	\centering
5	\includegraphics[width=0.95\textwidth]{figures/pipeline_overview.pdf}
6	\caption{Counterfactual episode collection and analysis pipeline. Each task instance is run under both pure strategies independently, producing episode-level labels via Algorithm~\ref{alg:labeling}.}
7	\label{fig:pipeline}
8	\end{figure*}
9	
10	Large language models deployed as interactive agents must repeatedly decide \emph{how} to compute: reason internally, or delegate to an external tool.
11	Existing routing methods---whether inserting API calls by perplexity reduction~\citep{toolformer-2023}, decomposing tasks into tool-augmented programs~\citep{art-2023,chameleon-2023}, or adaptively selecting reasoning depths~\citep{cogrouter-2026,ares-2026} and model tiers~\citep{mtrouter-2026,budget-aware-routing-2026}---share an implicit assumption: that routing signal stems from diverse sources and a learned router can exploit it. But before training a router, we should understand what mechanistic signal drives the routing preference. If signal collapses to a single dominant mechanism, a learned step-level router may not be the right solution.
12	
13	We propose an \emph{episode-level counterfactual diagnostic framework} to address this prior question. The framework compares pure-strategy outcomes (internal-only vs.\ deterministic-only) and introduces the Death Avoidance Factor (DAF) to decompose the routing score gap into death-avoidance and non-death components (\S\ref{sec:collection}--\ref{sec:daf}). Operating at episode granularity is essential: per-step oracle labeling degenerates under sparse terminal rewards (97.4\% tie rate in ScienceWorld; \S\ref{sec:collection}).
14	
15	Applied to ScienceWorld~\citep{scienceworld-2022}, the framework reveals that \textbf{78.9\% of non-tie routing labels arise from death asymmetry}---the internal strategy triggers a catastrophic failure while the deterministic strategy survives. This pattern replicates across three architecturally distinct model families (7--70B parameters) and intensifies at larger scale, where death avoidance accounts for the entire performance gap (\S\ref{sec:cross-model}--\ref{sec:agent-improvement}). Always-deterministic matches 96.3\% of oracle routing decisions; a trained step-level router fails to exceed this trivial baseline (\S\ref{sec:baselines}--\ref{sec:router-diagnostic}). Boundary probes on MATH and ALFWorld confirm the framework distinguishes qualitatively different mechanisms---including environments with no routing signal and those driven by information asymmetry (\S\ref{sec:cross-env}).
16	
17	Our contributions: (1)~An \textbf{episode-level counterfactual diagnostic framework} and the DAF metric that decompose routing signal into mechanistic components before any router is built, overcoming per-step oracle degeneracy in sparse-reward environments.
18	(2)~Evidence that \textbf{routing signal in ScienceWorld is death-dominated}: 78.9\% of non-tie labels trace to death asymmetry, replicated across three model families and two scales (7B and 70B). A ${\sim}$50-episode pilot suffices for practitioners to assess whether learned routing adds value (Appendix~\ref{app:decision-framework}).
19	(3)~\textbf{Boundary probes} on MATH and ALFWorld showing the framework can diagnose qualitatively different routing mechanisms, while clarifying that full quantitative validation remains specific to ScienceWorld.
20	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b19c5d9c-8379-4351-963d-606400b0dd42",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "b293e002-6a21-4f58-98bd-c43fd13d0300",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{figures/pipeline_overview.pdf}\n\\caption{Counterfactual episode collection and analysis pipeline. Each task instance is run under both pure strategies independently, producing episode-level labels via Algorithm~\\ref{alg:labeling}.}\n\\label{fig:pipeline}\n\\end{figure*}\n\nLarge language models deployed as interactive agents must repeatedly decide \\emph{how} to compute: reason internally, or delegate to an external tool.\nExisting routing methods---whether inserting API calls by perplexity reduction~\\citep{toolformer-2023}, decomposing tasks into tool-augmented programs~\\citep{art-2023,chameleon-2023}, or adaptively selecting reasoning depths~\\citep{cogrouter-2026,ares-2026} and model tiers~\\citep{mtrouter-2026,budget-aware-routing-2026}---share an implicit assumption: that routing signal stems from diverse sources and a learned router can exploit it. But before training a router, we should understand what mechanistic signal drives the routing preference. If signal collapses to a single dominant mechanism, a learned step-level router may not be the right solution.\n\nWe propose an \\emph{episode-level counterfactual diagnostic framework} to address this prior question. The framework compares pure-strategy outcomes (internal-only vs.\\ deterministic-only) and introduces the Death Avoidance Factor (DAF) to decompose the routing score gap into death-avoidance and non-death components (\\S\\ref{sec:collection}--\\ref{sec:daf}). Operating at episode granularity is essential: per-step oracle labeling degenerates under sparse terminal rewards (97.4\\% tie rate in ScienceWorld; \\S\\ref{sec:collection}).\n\nApplied to ScienceWorld~\\citep{scienceworld-2022}, the framework reveals that \\textbf{78.9\\% of non-tie routing labels arise from death asymmetry}---the internal strategy triggers a catastrophic failure while the deterministic strategy survives. This pattern replicates across three architecturally distinct model families (7--70B parameters) and intensifies at larger scale, where death avoidance accounts for the entire performance gap (\\S\\ref{sec:cross-model}--\\ref{sec:agent-improvement}). Always-deterministic matches 96.3\\% of oracle routing decisions; a trained step-level router fails to exceed this trivial baseline (\\S\\ref{sec:baselines}--\\ref{sec:router-diagnostic}). Boundary probes on MATH and ALFWorld confirm the framework distinguishes qualitatively different mechanisms---including environments with no routing signal and those driven by information asymmetry (\\S\\ref{sec:cross-env}).\n\nOur contributions: (1)~An \\textbf{episode-level counterfactual diagnostic framework} and the DAF metric that decompose routing signal into mechanistic components before any router is built, overcoming per-step oracle degeneracy in sparse-reward environments.\n(2)~Evidence that \\textbf{routing signal in ScienceWorld is death-dominated}: 78.9\\% of non-tie labels trace to death asymmetry, replicated across three model families and two scales (7B and 70B). A ${\\sim}$50-episode pilot suffices for practitioners to assess whether learned routing adds value (Appendix~\\ref{app:decision-framework}).\n(3)~\\textbf{Boundary probes} on MATH and ALFWorld showing the framework can diagnose qualitatively different routing mechanisms, while clarifying that full quantitative validation remains specific to ScienceWorld.\n",
      "numLines": 20,
      "startLine": 1,
      "totalLines": 20
    }
  },
  "sourceToolAssistantUUID": "b19c5d9c-8379-4351-963d-606400b0dd42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-25T15:16:39.650Z_

<details open><summary>🔧 Tool call — Read · `toolu_014K3NWPMRJXsbzmU6NWtLbf`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b293e002-6a21-4f58-98bd-c43fd13d0300",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "3e594da0-3267-45a4-a4fa-249c37205abd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 26 · 2026-05-25T15:16:39.655Z_

<details><summary>↩ Tool result · `toolu_014K3NWPMRJXsbzmU6NWtLbf`</summary>

```text
1	\section{Related Work}
2	
3	\paragraph{Tool-Augmented Agents and Adaptive Routing.}
4	Methods for augmenting LLMs with external tools span self-supervised invocation~\citep{toolformer-2023,toolace-2025}, task-level decomposition~\citep{art-2023,chameleon-2023}, and RL-based tool selection~\citep{retool-2025,tool-learning-survey-2024}. Concurrent work examines \emph{when} to invoke tools: \citet{when2tool-2026} analyze accuracy--latency tradeoffs, \citet{tool-use-tax-2026} quantify invocation overhead, and \citet{to-call-or-not-2026,tool-overuse-illusion-2026} investigate overuse patterns. On the routing side, adaptive methods range from learned halting~\citep{graves2016act} and token-level recursion~\citep{mixture-of-recursions-2025} to per-step depth adjustment~\citep{cogrouter-2026,ares-2026} and multi-turn model selection~\citep{mtrouter-2026}. Model-selection routing~\citep{routellm-2024,frugalgpt-2023,automix-2024} optimizes \emph{which} model to invoke based on query difficulty; \citet{budget-aware-routing-2026} train episode-level routing under sparse rewards via counterfactual rollouts---the closest setting to ours, though they focus on learning the router rather than diagnosing what signal it captures. All these approaches presuppose that diverse routing signals exist; our decomposition reveals that in ScienceWorld, a single mechanism accounts for 78.9\% of routing labels.
5	
6	\paragraph{Counterfactual Methods and Agent Environments.}
7	Prior work generates counterfactual explanations by perturbing individual actions~\citep{olson2021counterfactual,gajcin2023counterfactual,amitai2024explaining}; recent extensions target LLM agents via abstract state comparison~\citep{pona2025abstract}, axis-aligned perturbations~\citep{axis-2026}, and causal structure discovery~\citep{cso-2026}. These approaches explain \emph{why} an agent succeeded or failed on a single trajectory. We instead execute complete episodes under two strategies to decompose routing signal \emph{before} training. Counterfactual data augmentation~\citep{kaushik2020learning} edits inputs to improve robustness; we execute full counterfactual \emph{episodes} under controlled strategy variation, answering what \emph{type} of signal drives strategy preferences. ScienceWorld~\citep{scienceworld-2022} serves as our primary testbed; ALFWorld~\citep{alfworld-2021} and AgentBench~\citep{agentbench-2024} provide complementary evaluation. ReAct~\citep{react-2023} is our internal baseline; Reflexion~\citep{reflexion-2023} and LATS~\citep{lats-2024} extend it. The concurrent SALT~\citep{salt-2026} assigns step-level credit on ALFWorld, complementing our episode-level decomposition.
8	
9	\paragraph{Safe RL, Agent Safety, and Causal Inference.}
10	Death avoidance connects to safe RL~\citep{garcia2015comprehensive,achiam2017cpo}, shielding~\citep{alshiekh2018safe}, and the growing literature on LLM agent safety evaluation~\citep{ruan2024failures,saferoute-2025,agent-safetybench-2024}. Classical safe RL methods require known transition dynamics or a differentiable safety model, neither available for black-box LLM agents. Unlike token-level adaptive computation~\citep{mixture-of-depths-2024,xin2020deebert} and mixture-of-experts routing~\citep{switch-transformer-2022}, which optimize compute allocation at inference time, our framework diagnoses aggregate routing signal at episode granularity. Methodologically, our pure-strategy comparison is a simplified potential outcomes framework~\citep{rubin1974estimating}: executing both strategies under identical initial conditions eliminates confounding without structural causal models~\citep{pearl2009causality}, at the cost of requiring paired episode collection.
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3e594da0-3267-45a4-a4fa-249c37205abd",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "0882dbc8-d75e-4ae0-ab56-41e379dc222f",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\n\\paragraph{Tool-Augmented Agents and Adaptive Routing.}\nMethods for augmenting LLMs with external tools span self-supervised invocation~\\citep{toolformer-2023,toolace-2025}, task-level decomposition~\\citep{art-2023,chameleon-2023}, and RL-based tool selection~\\citep{retool-2025,tool-learning-survey-2024}. Concurrent work examines \\emph{when} to invoke tools: \\citet{when2tool-2026} analyze accuracy--latency tradeoffs, \\citet{tool-use-tax-2026} quantify invocation overhead, and \\citet{to-call-or-not-2026,tool-overuse-illusion-2026} investigate overuse patterns. On the routing side, adaptive methods range from learned halting~\\citep{graves2016act} and token-level recursion~\\citep{mixture-of-recursions-2025} to per-step depth adjustment~\\citep{cogrouter-2026,ares-2026} and multi-turn model selection~\\citep{mtrouter-2026}. Model-selection routing~\\citep{routellm-2024,frugalgpt-2023,automix-2024} optimizes \\emph{which} model to invoke based on query difficulty; \\citet{budget-aware-routing-2026} train episode-level routing under sparse rewards via counterfactual rollouts---the closest setting to ours, though they focus on learning the router rather than diagnosing what signal it captures. All these approaches presuppose that diverse routing signals exist; our decomposition reveals that in ScienceWorld, a single mechanism accounts for 78.9\\% of routing labels.\n\n\\paragraph{Counterfactual Methods and Agent Environments.}\nPrior work generates counterfactual explanations by perturbing individual actions~\\citep{olson2021counterfactual,gajcin2023counterfactual,amitai2024explaining}; recent extensions target LLM agents via abstract state comparison~\\citep{pona2025abstract}, axis-aligned perturbations~\\citep{axis-2026}, and causal structure discovery~\\citep{cso-2026}. These approaches explain \\emph{why} an agent succeeded or failed on a single trajectory. We instead execute complete episodes under two strategies to decompose routing signal \\emph{before} training. Counterfactual data augmentation~\\citep{kaushik2020learning} edits inputs to improve robustness; we execute full counterfactual \\emph{episodes} under controlled strategy variation, answering what \\emph{type} of signal drives strategy preferences. ScienceWorld~\\citep{scienceworld-2022} serves as our primary testbed; ALFWorld~\\citep{alfworld-2021} and AgentBench~\\citep{agentbench-2024} provide complementary evaluation. ReAct~\\citep{react-2023} is our internal baseline; Reflexion~\\citep{reflexion-2023} and LATS~\\citep{lats-2024} extend it. The concurrent SALT~\\citep{salt-2026} assigns step-level credit on ALFWorld, complementing our episode-level decomposition.\n\n\\paragraph{Safe RL, Agent Safety, and Causal Inference.}\nDeath avoidance connects to safe RL~\\citep{garcia2015comprehensive,achiam2017cpo}, shielding~\\citep{alshiekh2018safe}, and the growing literature on LLM agent safety evaluation~\\citep{ruan2024failures,saferoute-2025,agent-safetybench-2024}. Classical safe RL methods require known transition dynamics or a differentiable safety model, neither available for black-box LLM agents. Unlike token-level adaptive computation~\\citep{mixture-of-depths-2024,xin2020deebert} and mixture-of-experts routing~\\citep{switch-transformer-2022}, which optimize compute allocation at inference time, our framework diagnoses aggregate routing signal at episode granularity. Methodologically, our pure-strategy comparison is a simplified potential outcomes framework~\\citep{rubin1974estimating}: executing both strategies under identical initial conditions eliminates confounding without structural causal models~\\citep{pearl2009causality}, at the cost of requiring paired episode collection.\n",
      "numLines": 11,
      "startLine": 1,
      "totalLines": 11
    }
  },
  "sourceToolAssistantUUID": "3e594da0-3267-45a4-a4fa-249c37205abd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-25T15:16:40.152Z_

<details open><summary>🔧 Tool call — Read · `toolu_01ULMG9gVkJFjmztE6U8fxhT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0882dbc8-d75e-4ae0-ab56-41e379dc222f",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "1f06401e-f091-4adf-9fa3-81173518ac53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 28 · 2026-05-25T15:16:40.157Z_

<details><summary>↩ Tool result · `toolu_01ULMG9gVkJFjmztE6U8fxhT`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\begin{figure*}[t]
5	\begin{minipage}[t]{0.46\textwidth}
6	\centering
7	\scriptsize
8	\setlength{\tabcolsep}{4pt}
9	\begin{tabular}{@{}rrr@{}}
10	\toprule
11	$P$ & DAF($P$) & 95\% CI \\
12	\midrule
13	0 & 7.4\% & [$-39.4$, $82.5$] \\
14	1 & 14.8\% & [$-28.6$, $89.6$] \\
15	5 & 35.4\% & [$-1.8$, $92.7$] \\
16	10 & 50.4\% & [$18.5$, $93.3$] \\
17	25 & 70.7\% & [$48.0$, $96.3$] \\
18	50 & 82.6\% & [$67.2$, $98.2$] \\
19	100\textsuperscript{*} & 90.4\% & [$81.3$, $99.1$] \\
20	200 & 94.9\% & [$89.9$, $99.5$] \\
21	500 & 97.9\% & [$95.7$, $99.8$] \\
22	\bottomrule
23	\end{tabular}
24	\captionof{table}{Sensitivity of DAF to death penalty magnitude $P$. $\Delta_{\text{nd}} = 2.84$ is invariant; as $P$ increases, $\Delta_{\text{full}} \approx \delta P + \Delta_{\text{nd}}$ grows, mechanically increasing DAF. \textsuperscript{*}Default ScienceWorld setting. Bootstrap 95\% CIs ($B{=}10{,}000$).}
25	\label{tab:penalty-sensitivity}
26	\end{minipage}
27	\hfill
28	\begin{minipage}[t]{0.50\textwidth}
29	\centering
30	\includegraphics[width=\textwidth]{figures/label_decomposition.pdf}
31	\captionof{figure}{Episode-level label decomposition ($N{=}245$). Of 95 non-tie labels, 75 (78.9\%) arise from death asymmetry: 54 where death is the sole discriminator and 21 with co-occurring score differences. All 20 non-death labels originate from a single task type (\texttt{find-non-living-thing}).}
32	\label{fig:label-decomposition}
33	\end{minipage}
34	\end{figure*}
35	
36	Our diagnostic framework (Figure~\ref{fig:pipeline}) quantifies what drives routing signal in interactive environments through two components: (i)~episode-level counterfactual labeling that generates routing preferences from paired pure-strategy outcomes (\S\ref{sec:collection}--\ref{sec:labeling}); and (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\S\ref{sec:daf}). A supplementary Signal Concentration Index (SCI; Appendix~\ref{app:sci}) measures whether signal is concentrated in a few task types. Episode-level bootstrap resampling provides 95\% confidence intervals for all metrics.
37	
38	\subsection{Problem Setup}
39	\label{sec:problem-setup}
40	
41	Consider an interactive environment with observation space $\mathcal{O}$ and action space $\mathcal{A}$. An agent policy $\pi: \mathcal{O}^* \rightarrow \mathcal{A}$ maps observation histories to actions. We define two computation modes $\mathcal{M} = \{{\tt int}, {\tt det}\}$: \textbf{internal} (${\tt int}$), where the agent predicts intermediate observations via chain-of-thought reasoning (ReAct~\citep{react-2023}), with prediction errors compounding across steps; and \textbf{deterministic} (${\tt det}$), which uses the same LLM to generate candidate actions but evaluates them through privileged environment feedback---ground-truth simulator state in ScienceWorld, code interpreter in MATH, admissible-action enumeration in ALFWorld (see \S\ref{sec:cross-env} for environment-specific operationalizations). Crucially, the deterministic strategy does not provide optimal actions; it reduces observation uncertainty by grounding the LLM's choices in verified environment state rather than predicted state. These qualitative differences affect what routing signals the framework can detect. A \emph{routing policy} $\rho: \mathcal{O}^* \rightarrow \mathcal{M}$ selects which computation mode to use at each step; our analysis investigates what signal is available to learn $\rho$.
42	
43	\subsection{Counterfactual Episode Collection}
44	\label{sec:collection}
45	
46	Per-step oracle labeling degenerates under sparse terminal rewards: on ScienceWorld \citep{scienceworld-2022}, 97.4\% of steps (5{,}935 of 6{,}094 across 11 prescreened task types) produce identical intermediate scores, yielding no per-step routing signal. Episode-level comparison (directly measuring terminal outcomes) is therefore the principled granularity for sparse-reward environments.
47	
48	\paragraph{Pure-strategy trajectories.}
49	For a task instance $t$ and computation mode $m \in \mathcal{M}$, a \emph{pure-strategy trajectory} is the complete episode obtained by applying mode $m$ at every step:
50	\begin{equation}
51	    \tau_m^{(t)} = (o_1, a_1, o_2, a_2, \ldots, o_T, a_T)
52	\end{equation}
53	where $T \leq T_{\max}$ is the episode length (capped at $T_{\max} = 30$ steps). Both trajectories $\tau_{\tt int}^{(t)}$ and $\tau_{\tt det}^{(t)}$ are executed under identical initial conditions (same random seed, same task variation), so performance differences arise solely from the computation mode choice.
54	
55	Each trajectory $\tau$ yields a terminal score $s(\tau) \in \mathbb{Z}$ and a death indicator $d(\tau) \in \{0, 1\}$. When the agent dies ($d = 1$), the environment imposes a penalty: $s(\tau) = -P$ where $P > 0$ ($P = 100$ in ScienceWorld). The episode pair produces a tuple:
56	\begin{multline}
57	    \bigl(s^{\tt int}, s^{\tt det}, d^{\tt int}, d^{\tt det}\bigr) \triangleq \\
58	    \bigl(s(\tau_{\tt int}),\, s(\tau_{\tt det}),\, d(\tau_{\tt int}),\, d(\tau_{\tt det})\bigr)
59	\end{multline}
60	
61	We use Qwen2.5-7B-Instruct~\citep{qwen25-2024} (vLLM v0.21.0) on ScienceWorld \citep{scienceworld-2022}, a text-based environment spanning 30 task types with a $-100$ death penalty; complete prompt templates are provided in Appendix~\ref{app:prompt-templates}. After prescreening, we collect 245 episode pairs across 11 task types (20--40 per type). The framework is applicable to any environment where paired episodes under two computation modes can be collected with binary success/failure indicators. We apply it unchanged to ALFWorld and MATH in \S\ref{sec:math-contrast}--\ref{sec:cross-env}.
62	
63	\subsection{Episode-Level Labeling}
64	\label{sec:labeling}
65	
66	\begin{algorithm}[t]
67	\caption{Episode-Level Counterfactual Labeling}
68	\label{alg:labeling}
69	\begin{algorithmic}[1]
70	\REQUIRE Task instance $t$, computation modes $\mathcal{M} = \{{\tt int}, {\tt det}\}$
71	\ENSURE Label $\ell \in \{{\tt det\text{-}pref}, {\tt int\text{-}pref}, {\tt no\text{-}pref}\}$
72	\FOR{each $m \in \mathcal{M}$}
73	    \STATE Run episode $\tau_m$ with pure-strategy $m$
74	    \STATE Record score $s_m$ and death indicator $d_m$
75	\ENDFOR
76	\IF{$d_{\tt int} = 1$ \AND $d_{\tt det} = 0$}
77	    \STATE $\ell \leftarrow {\tt det\text{-}pref}$ \COMMENT{death asymmetry}
78	\ELSIF{$d_{\tt int} = 0$ \AND $d_{\tt det} = 1$}
79	    \STATE $\ell \leftarrow {\tt int\text{-}pref}$ \COMMENT{death asymmetry}
80	\ELSIF{$d_{\tt int} = d_{\tt det} = 1$}
81	    \STATE $\ell \leftarrow {\tt no\text{-}pref}$ \COMMENT{both dead}
82	\ELSIF{$s_{\tt det} > s_{\tt int}$}
83	    \STATE $\ell \leftarrow {\tt det\text{-}pref}$ \COMMENT{score comparison}
84	\ELSIF{$s_{\tt int} > s_{\tt det}$}
85	    \STATE $\ell \leftarrow {\tt int\text{-}pref}$ \COMMENT{score comparison}
86	\ELSE
87	    \STATE $\ell \leftarrow {\tt no\text{-}pref}$ \COMMENT{tied alive}
88	\ENDIF
89	\RETURN $\ell$
90	\end{algorithmic}
91	\end{algorithm}
92	
93	We define a labeling function $L$ that maps a counterfactual pair to a routing preference:
94	\begin{multline}
95	    L\!\bigl(\tau_{\tt int}^{(t)}, \tau_{\tt det}^{(t)}\bigr) \;\rightarrow \\
96	    \ell \in \{{\tt det\text{-}pref},\; {\tt int\text{-}pref},\; {\tt no\text{-}pref}\}
97	\end{multline}
98	
99	\begin{table}[t]
100	\centering
101	\small
102	\begin{tabular}{@{}lrr@{}}
103	\toprule
104	Condition & Death\% & $N$ \\
105	\midrule
106	Single-trial baseline & 42.9 & 245 \\
107	Reflexion ($3{\times}$) & 31.4 & 220 \\
108	Qwen2.5-72B ($10{\times}$) & 30.6 & 255 \\
109	Deterministic baseline & 16.3 & 245 \\
110	\midrule
111	\multicolumn{3}{@{}l}{\textit{10 death-prone tasks only:}} \\
112	Death-prone baseline & 48.0 & 200 \\
113	Retry ($5{\times}$) & 43.5 & 200 \\
114	\bottomrule
115	\end{tabular}
116	\caption{Internal-strategy death rates under improvement methods. Top: all 11 tasks. Bottom: 10 death-prone tasks (\texttt{find-non-living-thing} excluded). No intervention approaches deterministic-level safety.}
117	\label{tab:agent-improvement}
118	\end{table}
119	
120	The labeling function is \emph{death-aware}: it prioritizes survival over score, then compares scores among same-status episodes (Algorithm~\ref{alg:labeling}). Both-dead episodes receive \texttt{no\_preference} because ScienceWorld's fixed $-100$ penalty makes death timing uninformative. ScienceWorld scores are integer-valued, so we use exact (in)equality with no threshold. A quality audit confirming zero tie-breaking artifacts is in Appendix~\ref{app:labeling}. Label distributions are reported in \S\ref{sec:death-decomp}.
121	
122	\subsection{Death Avoidance Factor}
123	\label{sec:daf}
124	
125	To quantify the contribution of death avoidance to routing signal, we decompose the mean score gap between strategies. Let $\delta = \mathbb{E}[d^{\tt int}] - \mathbb{E}[d^{\tt det}]$ denote the death-rate differential and $\Delta_{\text{nd}}$ the mean score gap restricted to episodes where neither strategy dies. Partitioning episodes by death status, death-asymmetric episodes (where only one strategy dies) contribute a per-episode gap of $P + \bar{s}_{\text{surv}}$, where $\bar{s}_{\text{surv}}$ is the surviving strategy's mean score; when $\bar{s}_{\text{surv}} \ll P$ (in our data, $\bar{s}_{\text{surv}} = 0.87$, or $0.9\%$ of $P$), these episodes contribute ${\approx}\,\delta P$ in aggregate. The full gap thus decomposes as:
126	\begin{equation}
127	    \Delta_{\text{full}} \approx \underbrace{\delta \cdot P}_{\text{death contribution}} + \Delta_{\text{nd}}
128	\end{equation}
129	The approximation residual is $29.60 - 29.37 = 0.23$ ($0.8\%$ of $\Delta_{\text{full}}$).
130	
131	We define the Death Avoidance Factor (DAF) as the fraction of the full score gap attributable to death avoidance:
132	\begin{equation}
133	    \text{DAF} = 1 - \frac{\Delta_{\text{nd}}}{\Delta_{\text{full}}} \approx \frac{\delta P}{\delta P + \Delta_{\text{nd}}}
134	\end{equation}%
135	\footnote{When $\Delta_{\text{nd}} < 0$ (deterministic strategy scores lower than internal on non-death episodes), DAF exceeds 1; death avoidance then overcompensates for a non-death disadvantage.}
136	
137	DAF increases monotonically with $P$ (Table~\ref{tab:penalty-sensitivity}); we treat the label fraction (78.9\%) as the primary, penalty-invariant diagnostic. In ScienceWorld, $P$ affects only post-hoc score calculation; death rates and $\Delta_{\text{nd}}$ are $P$-invariant by design~\citep{ng1999policy}. Uncertainty is quantified via episode-level bootstrap ($B{=}10{,}000$, percentile 95\% CIs).
138	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1f06401e-f091-4adf-9fa3-81173518ac53",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "715b4637-561b-4348-a231-6e0c5ad57684",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\begin{minipage}[t]{0.46\\textwidth}\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{@{}rrr@{}}\n\\toprule\n$P$ & DAF($P$) & 95\\% CI \\\\\n\\midrule\n0 & 7.4\\% & [$-39.4$, $82.5$] \\\\\n1 & 14.8\\% & [$-28.6$, $89.6$] \\\\\n5 & 35.4\\% & [$-1.8$, $92.7$] \\\\\n10 & 50.4\\% & [$18.5$, $93.3$] \\\\\n25 & 70.7\\% & [$48.0$, $96.3$] \\\\\n50 & 82.6\\% & [$67.2$, $98.2$] \\\\\n100\\textsuperscript{*} & 90.4\\% & [$81.3$, $99.1$] \\\\\n200 & 94.9\\% & [$89.9$, $99.5$] \\\\\n500 & 97.9\\% & [$95.7$, $99.8$] \\\\\n\\bottomrule\n\\end{tabular}\n\\captionof{table}{Sensitivity of DAF to death penalty magnitude $P$. $\\Delta_{\\text{nd}} = 2.84$ is invariant; as $P$ increases, $\\Delta_{\\text{full}} \\approx \\delta P + \\Delta_{\\text{nd}}$ grows, mechanically increasing DAF. \\textsuperscript{*}Default ScienceWorld setting. Bootstrap 95\\% CIs ($B{=}10{,}000$).}\n\\label{tab:penalty-sensitivity}\n\\end{minipage}\n\\hfill\n\\begin{minipage}[t]{0.50\\textwidth}\n\\centering\n\\includegraphics[width=\\textwidth]{figures/label_decomposition.pdf}\n\\captionof{figure}{Episode-level label decomposition ($N{=}245$). Of 95 non-tie labels, 75 (78.9\\%) arise from death asymmetry: 54 where death is the sole discriminator and 21 with co-occurring score differences. All 20 non-death labels originate from a single task type (\\texttt{find-non-living-thing}).}\n\\label{fig:label-decomposition}\n\\end{minipage}\n\\end{figure*}\n\nOur diagnostic framework (Figure~\\ref{fig:pipeline}) quantifies what drives routing signal in interactive environments through two components: (i)~episode-level counterfactual labeling that generates routing preferences from paired pure-strategy outcomes (\\S\\ref{sec:collection}--\\ref{sec:labeling}); and (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\\S\\ref{sec:daf}). A supplementary Signal Concentration Index (SCI; Appendix~\\ref{app:sci}) measures whether signal is concentrated in a few task types. Episode-level bootstrap resampling provides 95\\% confidence intervals for all metrics.\n\n\\subsection{Problem Setup}\n\\label{sec:problem-setup}\n\nConsider an interactive environment with observation space $\\mathcal{O}$ and action space $\\mathcal{A}$. An agent policy $\\pi: \\mathcal{O}^* \\rightarrow \\mathcal{A}$ maps observation histories to actions. We define two computation modes $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$: \\textbf{internal} (${\\tt int}$), where the agent predicts intermediate observations via chain-of-thought reasoning (ReAct~\\citep{react-2023}), with prediction errors compounding across steps; and \\textbf{deterministic} (${\\tt det}$), which uses the same LLM to generate candidate actions but evaluates them through privileged environment feedback---ground-truth simulator state in ScienceWorld, code interpreter in MATH, admissible-action enumeration in ALFWorld (see \\S\\ref{sec:cross-env} for environment-specific operationalizations). Crucially, the deterministic strategy does not provide optimal actions; it reduces observation uncertainty by grounding the LLM's choices in verified environment state rather than predicted state. These qualitative differences affect what routing signals the framework can detect. A \\emph{routing policy} $\\rho: \\mathcal{O}^* \\rightarrow \\mathcal{M}$ selects which computation mode to use at each step; our analysis investigates what signal is available to learn $\\rho$.\n\n\\subsection{Counterfactual Episode Collection}\n\\label{sec:collection}\n\nPer-step oracle labeling degenerates under sparse terminal rewards: on ScienceWorld \\citep{scienceworld-2022}, 97.4\\% of steps (5{,}935 of 6{,}094 across 11 prescreened task types) produce identical intermediate scores, yielding no per-step routing signal. Episode-level comparison (directly measuring terminal outcomes) is therefore the principled granularity for sparse-reward environments.\n\n\\paragraph{Pure-strategy trajectories.}\nFor a task instance $t$ and computation mode $m \\in \\mathcal{M}$, a \\emph{pure-strategy trajectory} is the complete episode obtained by applying mode $m$ at every step:\n\\begin{equation}\n    \\tau_m^{(t)} = (o_1, a_1, o_2, a_2, \\ldots, o_T, a_T)\n\\end{equation}\nwhere $T \\leq T_{\\max}$ is the episode length (capped at $T_{\\max} = 30$ steps). Both trajectories $\\tau_{\\tt int}^{(t)}$ and $\\tau_{\\tt det}^{(t)}$ are executed under identical initial conditions (same random seed, same task variation), so performance differences arise solely from the computation mode choice.\n\nEach trajectory $\\tau$ yields a terminal score $s(\\tau) \\in \\mathbb{Z}$ and a death indicator $d(\\tau) \\in \\{0, 1\\}$. When the agent dies ($d = 1$), the environment imposes a penalty: $s(\\tau) = -P$ where $P > 0$ ($P = 100$ in ScienceWorld). The episode pair produces a tuple:\n\\begin{multline}\n    \\bigl(s^{\\tt int}, s^{\\tt det}, d^{\\tt int}, d^{\\tt det}\\bigr) \\triangleq \\\\\n    \\bigl(s(\\tau_{\\tt int}),\\, s(\\tau_{\\tt det}),\\, d(\\tau_{\\tt int}),\\, d(\\tau_{\\tt det})\\bigr)\n\\end{multline}\n\nWe use Qwen2.5-7B-Instruct~\\citep{qwen25-2024} (vLLM v0.21.0) on ScienceWorld \\citep{scienceworld-2022}, a text-based environment spanning 30 task types with a $-100$ death penalty; complete prompt templates are provided in Appendix~\\ref{app:prompt-templates}. After prescreening, we collect 245 episode pairs across 11 task types (20--40 per type). The framework is applicable to any environment where paired episodes under two computation modes can be collected with binary success/failure indicators. We apply it unchanged to ALFWorld and MATH in \\S\\ref{sec:math-contrast}--\\ref{sec:cross-env}.\n\n\\subsection{Episode-Level Labeling}\n\\label{sec:labeling}\n\n\\begin{algorithm}[t]\n\\caption{Episode-Level Counterfactual Labeling}\n\\label{alg:labeling}\n\\begin{algorithmic}[1]\n\\REQUIRE Task instance $t$, computation modes $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$\n\\ENSURE Label $\\ell \\in \\{{\\tt det\\text{-}pref}, {\\tt int\\text{-}pref}, {\\tt no\\text{-}pref}\\}$\n\\FOR{each $m \\in \\mathcal{M}$}\n    \\STATE Run episode $\\tau_m$ with pure-strategy $m$\n    \\STATE Record score $s_m$ and death indicator $d_m$\n\\ENDFOR\n\\IF{$d_{\\tt int} = 1$ \\AND $d_{\\tt det} = 0$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = 0$ \\AND $d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{both dead}\n\\ELSIF{$s_{\\tt det} > s_{\\tt int}$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSIF{$s_{\\tt int} > s_{\\tt det}$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSE\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{tied alive}\n\\ENDIF\n\\RETURN $\\ell$\n\\end{algorithmic}\n\\end{algorithm}\n\nWe define a labeling function $L$ that maps a counterfactual pair to a routing preference:\n\\begin{multline}\n    L\\!\\bigl(\\tau_{\\tt int}^{(t)}, \\tau_{\\tt det}^{(t)}\\bigr) \\;\\rightarrow \\\\\n    \\ell \\in \\{{\\tt det\\text{-}pref},\\; {\\tt int\\text{-}pref},\\; {\\tt no\\text{-}pref}\\}\n\\end{multline}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{@{}lrr@{}}\n\\toprule\nCondition & Death\\% & $N$ \\\\\n\\midrule\nSingle-trial baseline & 42.9 & 245 \\\\\nReflexion ($3{\\times}$) & 31.4 & 220 \\\\\nQwen2.5-72B ($10{\\times}$) & 30.6 & 255 \\\\\nDeterministic baseline & 16.3 & 245 \\\\\n\\midrule\n\\multicolumn{3}{@{}l}{\\textit{10 death-prone tasks only:}} \\\\\nDeath-prone baseline & 48.0 & 200 \\\\\nRetry ($5{\\times}$) & 43.5 & 200 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Internal-strategy death rates under improvement methods. Top: all 11 tasks. Bottom: 10 death-prone tasks (\\texttt{find-non-living-thing} excluded). No intervention approaches deterministic-level safety.}\n\\label{tab:agent-improvement}\n\\end{table}\n\nThe labeling function is \\emph{death-aware}: it prioritizes survival over score, then compares scores among same-status episodes (Algorithm~\\ref{alg:labeling}). Both-dead episodes receive \\texttt{no\\_preference} because ScienceWorld's fixed $-100$ penalty makes death timing uninformative. ScienceWorld scores are integer-valued, so we use exact (in)equality with no threshold. A quality audit confirming zero tie-breaking artifacts is in Appendix~\\ref{app:labeling}. Label distributions are reported in \\S\\ref{sec:death-decomp}.\n\n\\subsection{Death Avoidance Factor}\n\\label{sec:daf}\n\nTo quantify the contribution of death avoidance to routing signal, we decompose the mean score gap between strategies. Let $\\delta = \\mathbb{E}[d^{\\tt int}] - \\mathbb{E}[d^{\\tt det}]$ denote the death-rate differential and $\\Delta_{\\text{nd}}$ the mean score gap restricted to episodes where neither strategy dies. Partitioning episodes by death status, death-asymmetric episodes (where only one strategy dies) contribute a per-episode gap of $P + \\bar{s}_{\\text{surv}}$, where $\\bar{s}_{\\text{surv}}$ is the surviving strategy's mean score; when $\\bar{s}_{\\text{surv}} \\ll P$ (in our data, $\\bar{s}_{\\text{surv}} = 0.87$, or $0.9\\%$ of $P$), these episodes contribute ${\\approx}\\,\\delta P$ in aggregate. The full gap thus decomposes as:\n\\begin{equation}\n    \\Delta_{\\text{full}} \\approx \\underbrace{\\delta \\cdot P}_{\\text{death contribution}} + \\Delta_{\\text{nd}}\n\\end{equation}\nThe approximation residual is $29.60 - 29.37 = 0.23$ ($0.8\\%$ of $\\Delta_{\\text{full}}$).\n\nWe define the Death Avoidance Factor (DAF) as the fraction of the full score gap attributable to death avoidance:\n\\begin{equation}\n    \\text{DAF} = 1 - \\frac{\\Delta_{\\text{nd}}}{\\Delta_{\\text{full}}} \\approx \\frac{\\delta P}{\\delta P + \\Delta_{\\text{nd}}}\n\\end{equation}%\n\\footnote{When $\\Delta_{\\text{nd}} < 0$ (deterministic strategy scores lower than internal on non-death episodes), DAF exceeds 1; death avoidance then overcompensates for a non-death disadvantage.}\n\nDAF increases monotonically with $P$ (Table~\\ref{tab:penalty-sensitivity}); we treat the label fraction (78.9\\%) as the primary, penalty-invariant diagnostic. In ScienceWorld, $P$ affects only post-hoc score calculation; death rates and $\\Delta_{\\text{nd}}$ are $P$-invariant by design~\\citep{ng1999policy}. Uncertainty is quantified via episode-level bootstrap ($B{=}10{,}000$, percentile 95\\% CIs).\n",
      "numLines": 138,
      "startLine": 1,
      "totalLines": 138
    }
  },
  "sourceToolAssistantUUID": "1f06401e-f091-4adf-9fa3-81173518ac53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-25T15:16:40.622Z_

<details open><summary>🔧 Tool call — Read · `toolu_018eGgmEoMBccBiuxBCh834z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "715b4637-561b-4348-a231-6e0c5ad57684",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "1bbba60a-152d-4035-8def-331a8b0371b6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 30 · 2026-05-25T15:16:40.627Z_

<details><summary>↩ Tool result · `toolu_018eGgmEoMBccBiuxBCh834z`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\begin{figure}[t]
5	\centering
6	\includegraphics[width=0.75\columnwidth]{figures/fig1_daf_scatter.pdf}
7	\caption{Per-task death rate differential vs.\ performance gap ($n{=}11$ task types). The near-perfect correlation ($r = 0.97$) is a structural consequence of death dominance (DAF $\to 1 \Rightarrow r \to 1$), not an independent finding. The sole outlier (\texttt{find-non-living-thing}, diamond marker) has zero deaths; its $\Delta_{\text{full}} = +9.58$ arises entirely from non-death score differences.}
8	\label{fig:decomposition}
9	\end{figure}
10	
11	We analyze 11 of ScienceWorld's 30 task types (245 episodes); the 19 excluded types lack actionable routing signal due to development contamination (5), taxonomic redundancy (7), or agent-floor performance (7). An anti-cherry-picking analysis confirms death dominance holds in 18 of these 19 types ($\overline{\Delta\text{DR}} = +38.2$\,pp $>$ included tasks' $+28.7$\,pp; Appendix~\ref{app:per-task}), with extended validation on representative excluded tasks in Appendix~\ref{app:extended-validation}.
12	
13	\subsection{Death Avoidance Decomposition}
14	\label{sec:death-decomp}
15	
16	\begin{figure}[t]
17	\centering
18	\includegraphics[width=0.95\columnwidth]{figures/death_action_timeline.pdf}
19	\vspace{-2mm}
20	\caption{Action sequences for 6 representative death episodes. The fatal \texttt{focus on} (arrow) appears in final steps after long \texttt{connect} sequences (``connect loop $\to$ fatal focus'').}
21	\label{fig:death-timeline}
22	\end{figure}
23	
24	\begin{table}[t]
25	\centering
26	\scriptsize
27	\setlength{\tabcolsep}{2.5pt}
28	\begin{tabular}{@{}lrrccc@{}}
29	\toprule
30	Task & $n$ & $\Delta_\text{full}$ & D\%\textsubscript{int} & D\%\textsubscript{det} & D / I / N \\
31	\midrule
32	id-life-stages-1       & 20  & $+47.50$ & 55   & 10   & 9 / 0 / 11  \\
33	lifespan-long          & 25  & $+44.00$ & 56   & 16   & 11 / 1 / 13 \\
34	lifespan-l-then-s      & 20  & $+40.80$ & 45   & 10   & 8 / 1 / 11  \\
35	inclined-plane         & 20  & $+36.00$ & 55   & 20   & 7 / 0 / 13  \\
36	freeze                 & 20  & $+30.50$ & 55   & 25   & 6 / 0 / 14  \\
37	meas-melt-point        & 20  & $+30.05$ & 55   & 25   & 6 / 0 / 14  \\
38	id-life-stages-2       & 20  & $+30.00$ & 50   & 20   & 6 / 0 / 14  \\
39	find-animal            & 20  & $+26.65$ & 50   & 25   & 5 / 0 / 15  \\
40	grow-fruit             & 20  & $+25.10$ & 45   & 20   & 6 / 1 / 13  \\
41	chem-mix               & 20  & $+21.80$ & 45   & 25   & 6 / 2 / 12  \\
42	\midrule
43	find-non-living$^\dagger$ & 40 & $+9.58$ & 0  & 0    & 16 / 4 / 20 \\
44	\midrule
45	\textbf{All (11 tasks)} & \textbf{245} & $\mathbf{+29.60}$ & \textbf{42.9} & \textbf{16.3} & \textbf{86 / 9 / 150} \\
46	\bottomrule
47	\end{tabular}
48	\caption{Per-task decomposition. D\%: death rate for internal/deterministic. D/I/N: det-preferred / int-preferred / no-preference labels. $\dagger$\,Only task with zero deaths; $n{=}40$ (two batches).}
49	\label{tab:per-task}
50	\end{table}
51	
52	Of the 95 non-tie routing labels (Figure~\ref{fig:label-decomposition}), 75 (78.9\%; 95\% CI: $[70.7\%, 87.0\%]$, episode-level bootstrap) arise from death asymmetry: the internal strategy triggers a catastrophic $-100$ penalty while the deterministic strategy survives. This penalty-independent label fraction is the primary diagnostic metric. Of these, 54 are sole-signal labels where death was the only discriminator; at $P{=}0$ these reduce to ties, but the labeling function itself is penalty-independent (Algorithm~\ref{alg:labeling}).
53	
54	DAF $= 90.4\%$ at $P{=}100$ ($\Delta_{\text{full}} = +29.60$, $\Delta_{\text{nd}} = +2.84$; 95\% CI$_{\text{DAF}}$: $[81.3\%, 99.1\%]$, episode-level bootstrap). The 78.9\% label fraction provides the more robust, penalty-invariant characterization (\S\ref{sec:daf}).
55	
56	\paragraph{Per-task structure.}
57	The internal strategy dies in 42.9\% of episodes versus 16.3\% for deterministic; all 105 internal deaths are triggered by the \texttt{focus on} action (Appendix~\ref{app:failure-modes}). Per-task $\Delta$DR correlates with $\Delta_{\text{full}}$ at $r = 0.97$ (Figure~\ref{fig:decomposition}; leave-one-out and bootstrap robustness in Appendix~\ref{app:correlation}), a structural consequence of DAF$\to 1$ rather than an independent finding. Figure~\ref{fig:death-timeline} illustrates the typical death trajectory.
58	
59	\paragraph{Binary structure and robustness.}
60	All 10 death-prone task types produce 100\% death-asymmetry labels; only \texttt{find-non-living-thing} (zero deaths) produces non-death signal (SCI $= 0.21$; Appendix~\ref{app:sci}; case study in Appendix~\ref{app:non-death-case-study}). Leave-one-task-out analysis (Table~\ref{tab:loto-daf}) confirms robustness: removing any single death-prone task changes DAF by at most 3.0~pp. Bootstrap 95\% CIs: DAF $[81.3\%, 99.1\%]$; cluster-robust $[73.3\%, 100.0\%]$ ($K{=}11$; Appendix~\ref{app:wild-cluster}). Two independent replications (Gemma-2-9B-it, DAF${=}89.7\%$; seed=123, DAF${=}89.7\%$) converge within 0.7~pp.
61	
62	\subsection{Multi-Model Validation (7--9B Tier)}
63	\label{sec:cross-model}
64	
65	Llama-3.1-8B~\citep{llama3-2024} ($N{=}220$) and Gemma-2-9B-it~\citep{gemma2-2024} ($N{=}220$) independently replicate death dominance: DAF $= 88.2\%$ and $89.7\%$ respectively, with direction consistency 10/10 on death-prone tasks (Appendix~\ref{app:cross-model}; per-task CIs across all 30 tasks in Appendix~\ref{app:per-task-ci}). Three architecturally distinct model families, Qwen (Alibaba), Llama (Meta), and Gemma (Google), converge on DAF $88$--$90\%$ with a spread of only 2.2~pp, despite differences in pretraining data, architecture, and tokenization. This narrow convergence suggests that death dominance reflects an environment-level property rather than a model-specific artifact. Scaling $10{\times}$ to two 70B-class models (\S\ref{sec:agent-improvement}) yields DAF${=}92.4$--$101.0\%$, indicating that the pattern persists---and may intensify---at larger scale.
66	
67	\begin{table}[t]
68	\centering
69	\scriptsize
70	\setlength{\tabcolsep}{2pt}
71	\resizebox{\columnwidth}{!}{%
72	\begin{tabular}{@{}llcrrrcl@{}}
73	\toprule
74	Model & Env & $n$ & Int DR & Det DR & $\Delta$DR & DAF [95\% CI] & Signal \\
75	\midrule
76	Qwen2.5-7B & SW & 245 & 42.9 & 16.3 & +26.5 & 90.4 [81.3, 99.1] & death \\
77	Llama-3.1-8B & SW & 220 & 41.4 & 11.4 & +30.0 & 88.2 [80.2, 95.1] & death \\
78	Gemma-2-9B & SW & 220 & 36.4 & 14.1 & +22.3 & 89.7 [79.5, 98.4] & death \\
79	Qwen2.5-72B & SW & 255 & 30.6 & 2.8 & +27.8 & 92.4 [86.1, 97.9] & death \\
80	Llama-70B & SW & 220 & 48.6 & 20.0 & +28.6 & 101.0 [95.3, 107.5] & death \\
81	\midrule
82	Qwen2.5-7B & ALF & 135 & 0 & 0 & 0 & 0 & info-asym \\
83	Llama-3.1-8B & ALF & 135 & 0 & 0 & 0 & 0 & info-asym \\
84	\midrule
85	Qwen2.5-7B & MATH & 795 & --- & --- & --- & --- & none \\
86	\bottomrule
87	\end{tabular}}
88	\caption{Cross-model and cross-environment summary. SW = ScienceWorld, ALF = ALFWorld. Death dominance replicates across three 7--9B families and intensifies under $10{\times}$ scaling; ALFWorld shows information-asymmetry signal; MATH shows none. DR = death rate (\%).}
89	\label{tab:cross-model-env}
90	\end{table}
91	
92	\begin{table}[t]
93	\centering
94	\scriptsize
95	\setlength{\tabcolsep}{3pt}
96	\begin{tabular}{@{}lrrr@{}}
97	\toprule
98	Removed Task & $N_\text{rem}$ & DAF (\%) & $\Delta$ (pp) \\
99	\midrule
100	(none, full) & 245 & 78.9 & --- \\
101	\midrule
102	Find Non-Living$^\dagger$ & 205 & 100.0 & +21.1 \\
103	Lifespan Longest & 220 & 75.9 & $-$3.0 \\
104	Life Stages 1 & 225 & 76.7 & $-$2.2 \\
105	Lifespan Long+Short & 225 & 76.7 & $-$2.2 \\
106	Chemistry Mix & 225 & 77.0 & $-$1.9 \\
107	Grow Fruit & 225 & 77.3 & $-$1.7 \\
108	Inclined Plane & 225 & 77.3 & $-$1.7 \\
109	Freeze & 225 & 77.5 & $-$1.4 \\
110	Life Stages 2 & 225 & 77.5 & $-$1.4 \\
111	Melt Pt Unknown & 225 & 77.5 & $-$1.4 \\
112	Find Animal & 225 & 77.8 & $-$1.2 \\
113	\bottomrule
114	\end{tabular}
115	\caption{Leave-one-task-out DAF sensitivity (label fraction). Removing any death-prone task changes DAF by $\leq$3.0\,pp. $\dagger$\,Sole death-free task; removal raises DAF to 100\% by construction.}
116	\label{tab:loto-daf}
117	\end{table}
118	
119	\subsection{Agent Improvement Baselines}
120	\label{sec:agent-improvement}
121	
122	We test whether agent-level improvement reduces death dominance (Table~\ref{tab:agent-improvement}). Retry ($N{=}5$) yields marginal reduction ($43.5\%$ vs.\ $48.0\%$). Reflexion~\citep{reflexion-2023} reduces death to $31.4\%$ but the gap to deterministic remains $15.1$~pp; under matched-episode analysis ($N{=}3$), $\Delta_{\text{nd}} = -0.47$, yielding DAF${}>100\%$. Scaling to Qwen2.5-72B ($N{=}255$) reduces death rate to $30.6\%$ with DAF $= 92.4\%$ (95\% CI: $[86.1\%, 97.9\%]$). A second 70B model, Llama-3.1-70B ($N{=}220$), yields DAF $= 101.0\%$ ($[95.3\%, 107.5\%]$): death avoidance more than fully accounts for the gap. Both 70B-class models suggest that scaling does not attenuate death dominance.
123	
124	\paragraph{Dose-response analysis.}
125	We extend both interventions to $N{=}5$ trials on death-prone tasks ($n{=}200$; Figure~\ref{fig:dose-response}). Retry is nearly flat ($48.0\% \to 43.5\%$). Reflexion drops steeply to $34.0\%$ at $N{=}3$ ($\Delta = -13.5$~pp, $p = 0.003$) then stabilizes ($34$--$36.5\%$ for $N \geq 3$, pairwise $p > 0.5$); both the decline and plateau are well-powered (MDE ${\sim}8$~pp at 80\% power; Appendix~\ref{app:dose-response}).
126	
127	\begin{figure}[t]
128	\centering
129	\includegraphics[width=\columnwidth]{figures/dose_response.pdf}
130	\caption{Death rate vs.\ trial count for Retry and Reflexion on 10 death-prone tasks ($n{=}200$). Reflexion drops steeply through $N{=}3$ then plateaus; Retry is nearly flat. Horizontal lines: 72B ($30.6\%$) and deterministic ($16.3\%$) baselines. Error bands: Wilson 95\% CIs.}
131	\label{fig:dose-response}
132	\end{figure}
133	
134	\subsection{Cross-Environment Boundary Probes}
135	\label{sec:math-contrast}
136	\label{sec:cross-env}
137	
138	We probe two environments as boundary cases to test the framework's specificity (Figure~\ref{fig:signal-reversal}). On MATH Level~4--5~\citep{math-2021} ($N{=}795$), internal reasoning and code-interpreter accuracy are near-identical ($73.5\%$ vs.\ $73.0\%$, $p = 0.81$): without a catastrophic failure mechanism, no routing signal emerges despite substantial task difficulty. ALFWorld~\citep{alfworld-2021} (135 games, no death mechanism, DAF $= 0\%$) shows 94.6\% of non-tie labels favoring the information-advantaged strategy (which enumerates admissible actions); Llama-3.1-8B replicates at 100\%. The framework identifies this qualitatively different mechanism---information asymmetry rather than death avoidance---without modification, indicating that DAF correctly attributes zero signal to death when none exists (full label distributions and per-task breakdowns in Appendix~\ref{app:cross-env-details}).
139	
140	\subsection{Baselines}
141	\label{sec:baselines}
142	
143	Always-deterministic ($-9.47$) outperforms always-internal ($-39.07$) by 29.60 points (Table~\ref{tab:baselines}). Random routing ($-22.38$) falls between the two pure strategies, confirming that the gap is not an artifact of evaluation methodology. The oracle improves only to $-6.58$, with 96.3\% of decisions matching always-deterministic, an \emph{oracle degeneracy} where perfect per-episode foresight provides marginal benefit over the trivial always-deterministic baseline (Appendix~\ref{sec:threshold-routing}).
144	
145	\subsection{Router Training: Inconclusive Results}
146	\label{sec:router-diagnostic}
147	
148	A Qwen3 LoRA router (0.6B--4B; Appendix~\ref{app:router-details}) trained on counterfactual labels shows flat step-level balanced accuracy ($56$--$59\%$) across all model scales; episode-level evaluation yields $47.1 \pm 2.2\%$, below majority-vote.\footnote{Consistent with noisy-label bounds~\citep{natarajan2013learning}: ${\sim}$88\% of step-level labels are uninformative with 90.5\%/3.7\% class imbalance (Appendix~\ref{app:seed-robustness}).} Leave-one-task-out degrades to chance ($49.2\%$), suggesting signal is a per-task-type constant rather than a learnable function of step-level observations. Deployed end-to-end, the best router (4B) scores $-10.70$, not exceeding always-deterministic ($-9.47$); this negative result is consistent with the death-dominance finding, as death avoidance cannot be predicted from pre-episode features when it depends on multi-step trajectory dynamics. Additional ablations (capacity scaling, generative routing, reasoning depth) are in Appendix~\ref{app:ablations}.
149	
150	\begin{table}[t]
151	\centering
152	\small
153	\resizebox{\columnwidth}{!}{%
154	\begin{tabular}{@{}lccc@{}}
155	\toprule
156	Strategy & Score & 95\% CI & Death \% \\
157	\midrule
158	Always-Internal & $-39.07$ & [$-46.40$, $-32.27$] & 42.9 \\
159	Always-Deterministic & $-9.47$ & [$-14.71$, $-4.29$] & 16.3 \\
160	Random & $-22.38$ & [$-28.67$, $-15.75$] & 27.8 \\
161	Oracle & $-6.58$ & [$-11.54$, $-1.70$] & 14.3 \\
162	\midrule
163	Trained Router$^\dagger$ & $-10.70$ & [$-16.33$, $-5.27$] & 17.6 \\
164	\bottomrule
165	\end{tabular}}
166	\caption{Episode-weighted mean scores on ScienceWorld (11 task types, 245 episodes). $\dagger$\,Single seed (42); see Appendix~\ref{app:seed-robustness} for 8-seed robustness.}
167	\label{tab:baselines}
168	\end{table}
169	
170	\begin{figure}[t]
171	\centering
172	\includegraphics[width=0.95\columnwidth]{figures/signal_reversal.pdf}
173	\vspace{-2mm}
174	\caption{Cross-environment label distributions. ScienceWorld and ALFWorld both favor deterministic via different mechanisms (death avoidance vs.\ information asymmetry); MATH shows no routing signal.}
175	\label{fig:signal-reversal}
176	\end{figure}
177	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1bbba60a-152d-4035-8def-331a8b0371b6",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "f9d61043-03ed-42a0-a7a1-96794ef4e5e4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig1_daf_scatter.pdf}\n\\caption{Per-task death rate differential vs.\\ performance gap ($n{=}11$ task types). The near-perfect correlation ($r = 0.97$) is a structural consequence of death dominance (DAF $\\to 1 \\Rightarrow r \\to 1$), not an independent finding. The sole outlier (\\texttt{find-non-living-thing}, diamond marker) has zero deaths; its $\\Delta_{\\text{full}} = +9.58$ arises entirely from non-death score differences.}\n\\label{fig:decomposition}\n\\end{figure}\n\nWe analyze 11 of ScienceWorld's 30 task types (245 episodes); the 19 excluded types lack actionable routing signal due to development contamination (5), taxonomic redundancy (7), or agent-floor performance (7). An anti-cherry-picking analysis confirms death dominance holds in 18 of these 19 types ($\\overline{\\Delta\\text{DR}} = +38.2$\\,pp $>$ included tasks' $+28.7$\\,pp; Appendix~\\ref{app:per-task}), with extended validation on representative excluded tasks in Appendix~\\ref{app:extended-validation}.\n\n\\subsection{Death Avoidance Decomposition}\n\\label{sec:death-decomp}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/death_action_timeline.pdf}\n\\vspace{-2mm}\n\\caption{Action sequences for 6 representative death episodes. The fatal \\texttt{focus on} (arrow) appears in final steps after long \\texttt{connect} sequences (``connect loop $\\to$ fatal focus'').}\n\\label{fig:death-timeline}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2.5pt}\n\\begin{tabular}{@{}lrrccc@{}}\n\\toprule\nTask & $n$ & $\\Delta_\\text{full}$ & D\\%\\textsubscript{int} & D\\%\\textsubscript{det} & D / I / N \\\\\n\\midrule\nid-life-stages-1       & 20  & $+47.50$ & 55   & 10   & 9 / 0 / 11  \\\\\nlifespan-long          & 25  & $+44.00$ & 56   & 16   & 11 / 1 / 13 \\\\\nlifespan-l-then-s      & 20  & $+40.80$ & 45   & 10   & 8 / 1 / 11  \\\\\ninclined-plane         & 20  & $+36.00$ & 55   & 20   & 7 / 0 / 13  \\\\\nfreeze                 & 20  & $+30.50$ & 55   & 25   & 6 / 0 / 14  \\\\\nmeas-melt-point        & 20  & $+30.05$ & 55   & 25   & 6 / 0 / 14  \\\\\nid-life-stages-2       & 20  & $+30.00$ & 50   & 20   & 6 / 0 / 14  \\\\\nfind-animal            & 20  & $+26.65$ & 50   & 25   & 5 / 0 / 15  \\\\\ngrow-fruit             & 20  & $+25.10$ & 45   & 20   & 6 / 1 / 13  \\\\\nchem-mix               & 20  & $+21.80$ & 45   & 25   & 6 / 2 / 12  \\\\\n\\midrule\nfind-non-living$^\\dagger$ & 40 & $+9.58$ & 0  & 0    & 16 / 4 / 20 \\\\\n\\midrule\n\\textbf{All (11 tasks)} & \\textbf{245} & $\\mathbf{+29.60}$ & \\textbf{42.9} & \\textbf{16.3} & \\textbf{86 / 9 / 150} \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-task decomposition. D\\%: death rate for internal/deterministic. D/I/N: det-preferred / int-preferred / no-preference labels. $\\dagger$\\,Only task with zero deaths; $n{=}40$ (two batches).}\n\\label{tab:per-task}\n\\end{table}\n\nOf the 95 non-tie routing labels (Figure~\\ref{fig:label-decomposition}), 75 (78.9\\%; 95\\% CI: $[70.7\\%, 87.0\\%]$, episode-level bootstrap) arise from death asymmetry: the internal strategy triggers a catastrophic $-100$ penalty while the deterministic strategy survives. This penalty-independent label fraction is the primary diagnostic metric. Of these, 54 are sole-signal labels where death was the only discriminator; at $P{=}0$ these reduce to ties, but the labeling function itself is penalty-independent (Algorithm~\\ref{alg:labeling}).\n\nDAF $= 90.4\\%$ at $P{=}100$ ($\\Delta_{\\text{full}} = +29.60$, $\\Delta_{\\text{nd}} = +2.84$; 95\\% CI$_{\\text{DAF}}$: $[81.3\\%, 99.1\\%]$, episode-level bootstrap). The 78.9\\% label fraction provides the more robust, penalty-invariant characterization (\\S\\ref{sec:daf}).\n\n\\paragraph{Per-task structure.}\nThe internal strategy dies in 42.9\\% of episodes versus 16.3\\% for deterministic; all 105 internal deaths are triggered by the \\texttt{focus on} action (Appendix~\\ref{app:failure-modes}). Per-task $\\Delta$DR correlates with $\\Delta_{\\text{full}}$ at $r = 0.97$ (Figure~\\ref{fig:decomposition}; leave-one-out and bootstrap robustness in Appendix~\\ref{app:correlation}), a structural consequence of DAF$\\to 1$ rather than an independent finding. Figure~\\ref{fig:death-timeline} illustrates the typical death trajectory.\n\n\\paragraph{Binary structure and robustness.}\nAll 10 death-prone task types produce 100\\% death-asymmetry labels; only \\texttt{find-non-living-thing} (zero deaths) produces non-death signal (SCI $= 0.21$; Appendix~\\ref{app:sci}; case study in Appendix~\\ref{app:non-death-case-study}). Leave-one-task-out analysis (Table~\\ref{tab:loto-daf}) confirms robustness: removing any single death-prone task changes DAF by at most 3.0~pp. Bootstrap 95\\% CIs: DAF $[81.3\\%, 99.1\\%]$; cluster-robust $[73.3\\%, 100.0\\%]$ ($K{=}11$; Appendix~\\ref{app:wild-cluster}). Two independent replications (Gemma-2-9B-it, DAF${=}89.7\\%$; seed=123, DAF${=}89.7\\%$) converge within 0.7~pp.\n\n\\subsection{Multi-Model Validation (7--9B Tier)}\n\\label{sec:cross-model}\n\nLlama-3.1-8B~\\citep{llama3-2024} ($N{=}220$) and Gemma-2-9B-it~\\citep{gemma2-2024} ($N{=}220$) independently replicate death dominance: DAF $= 88.2\\%$ and $89.7\\%$ respectively, with direction consistency 10/10 on death-prone tasks (Appendix~\\ref{app:cross-model}; per-task CIs across all 30 tasks in Appendix~\\ref{app:per-task-ci}). Three architecturally distinct model families, Qwen (Alibaba), Llama (Meta), and Gemma (Google), converge on DAF $88$--$90\\%$ with a spread of only 2.2~pp, despite differences in pretraining data, architecture, and tokenization. This narrow convergence suggests that death dominance reflects an environment-level property rather than a model-specific artifact. Scaling $10{\\times}$ to two 70B-class models (\\S\\ref{sec:agent-improvement}) yields DAF${=}92.4$--$101.0\\%$, indicating that the pattern persists---and may intensify---at larger scale.\n\n\\begin{table}[t]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcrrrcl@{}}\n\\toprule\nModel & Env & $n$ & Int DR & Det DR & $\\Delta$DR & DAF [95\\% CI] & Signal \\\\\n\\midrule\nQwen2.5-7B & SW & 245 & 42.9 & 16.3 & +26.5 & 90.4 [81.3, 99.1] & death \\\\\nLlama-3.1-8B & SW & 220 & 41.4 & 11.4 & +30.0 & 88.2 [80.2, 95.1] & death \\\\\nGemma-2-9B & SW & 220 & 36.4 & 14.1 & +22.3 & 89.7 [79.5, 98.4] & death \\\\\nQwen2.5-72B & SW & 255 & 30.6 & 2.8 & +27.8 & 92.4 [86.1, 97.9] & death \\\\\nLlama-70B & SW & 220 & 48.6 & 20.0 & +28.6 & 101.0 [95.3, 107.5] & death \\\\\n\\midrule\nQwen2.5-7B & ALF & 135 & 0 & 0 & 0 & 0 & info-asym \\\\\nLlama-3.1-8B & ALF & 135 & 0 & 0 & 0 & 0 & info-asym \\\\\n\\midrule\nQwen2.5-7B & MATH & 795 & --- & --- & --- & --- & none \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-model and cross-environment summary. SW = ScienceWorld, ALF = ALFWorld. Death dominance replicates across three 7--9B families and intensifies under $10{\\times}$ scaling; ALFWorld shows information-asymmetry signal; MATH shows none. DR = death rate (\\%).}\n\\label{tab:cross-model-env}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}lrrr@{}}\n\\toprule\nRemoved Task & $N_\\text{rem}$ & DAF (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\n(none, full) & 245 & 78.9 & --- \\\\\n\\midrule\nFind Non-Living$^\\dagger$ & 205 & 100.0 & +21.1 \\\\\nLifespan Longest & 220 & 75.9 & $-$3.0 \\\\\nLife Stages 1 & 225 & 76.7 & $-$2.2 \\\\\nLifespan Long+Short & 225 & 76.7 & $-$2.2 \\\\\nChemistry Mix & 225 & 77.0 & $-$1.9 \\\\\nGrow Fruit & 225 & 77.3 & $-$1.7 \\\\\nInclined Plane & 225 & 77.3 & $-$1.7 \\\\\nFreeze & 225 & 77.5 & $-$1.4 \\\\\nLife Stages 2 & 225 & 77.5 & $-$1.4 \\\\\nMelt Pt Unknown & 225 & 77.5 & $-$1.4 \\\\\nFind Animal & 225 & 77.8 & $-$1.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Leave-one-task-out DAF sensitivity (label fraction). Removing any death-prone task changes DAF by $\\leq$3.0\\,pp. $\\dagger$\\,Sole death-free task; removal raises DAF to 100\\% by construction.}\n\\label{tab:loto-daf}\n\\end{table}\n\n\\subsection{Agent Improvement Baselines}\n\\label{sec:agent-improvement}\n\nWe test whether agent-level improvement reduces death dominance (Table~\\ref{tab:agent-improvement}). Retry ($N{=}5$) yields marginal reduction ($43.5\\%$ vs.\\ $48.0\\%$). Reflexion~\\citep{reflexion-2023} reduces death to $31.4\\%$ but the gap to deterministic remains $15.1$~pp; under matched-episode analysis ($N{=}3$), $\\Delta_{\\text{nd}} = -0.47$, yielding DAF${}>100\\%$. Scaling to Qwen2.5-72B ($N{=}255$) reduces death rate to $30.6\\%$ with DAF $= 92.4\\%$ (95\\% CI: $[86.1\\%, 97.9\\%]$). A second 70B model, Llama-3.1-70B ($N{=}220$), yields DAF $= 101.0\\%$ ($[95.3\\%, 107.5\\%]$): death avoidance more than fully accounts for the gap. Both 70B-class models suggest that scaling does not attenuate death dominance.\n\n\\paragraph{Dose-response analysis.}\nWe extend both interventions to $N{=}5$ trials on death-prone tasks ($n{=}200$; Figure~\\ref{fig:dose-response}). Retry is nearly flat ($48.0\\% \\to 43.5\\%$). Reflexion drops steeply to $34.0\\%$ at $N{=}3$ ($\\Delta = -13.5$~pp, $p = 0.003$) then stabilizes ($34$--$36.5\\%$ for $N \\geq 3$, pairwise $p > 0.5$); both the decline and plateau are well-powered (MDE ${\\sim}8$~pp at 80\\% power; Appendix~\\ref{app:dose-response}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/dose_response.pdf}\n\\caption{Death rate vs.\\ trial count for Retry and Reflexion on 10 death-prone tasks ($n{=}200$). Reflexion drops steeply through $N{=}3$ then plateaus; Retry is nearly flat. Horizontal lines: 72B ($30.6\\%$) and deterministic ($16.3\\%$) baselines. Error bands: Wilson 95\\% CIs.}\n\\label{fig:dose-response}\n\\end{figure}\n\n\\subsection{Cross-Environment Boundary Probes}\n\\label{sec:math-contrast}\n\\label{sec:cross-env}\n\nWe probe two environments as boundary cases to test the framework's specificity (Figure~\\ref{fig:signal-reversal}). On MATH Level~4--5~\\citep{math-2021} ($N{=}795$), internal reasoning and code-interpreter accuracy are near-identical ($73.5\\%$ vs.\\ $73.0\\%$, $p = 0.81$): without a catastrophic failure mechanism, no routing signal emerges despite substantial task difficulty. ALFWorld~\\citep{alfworld-2021} (135 games, no death mechanism, DAF $= 0\\%$) shows 94.6\\% of non-tie labels favoring the information-advantaged strategy (which enumerates admissible actions); Llama-3.1-8B replicates at 100\\%. The framework identifies this qualitatively different mechanism---information asymmetry rather than death avoidance---without modification, indicating that DAF correctly attributes zero signal to death when none exists (full label distributions and per-task breakdowns in Appendix~\\ref{app:cross-env-details}).\n\n\\subsection{Baselines}\n\\label{sec:baselines}\n\nAlways-deterministic ($-9.47$) outperforms always-internal ($-39.07$) by 29.60 points (Table~\\ref{tab:baselines}). Random routing ($-22.38$) falls between the two pure strategies, confirming that the gap is not an artifact of evaluation methodology. The oracle improves only to $-6.58$, with 96.3\\% of decisions matching always-deterministic, an \\emph{oracle degeneracy} where perfect per-episode foresight provides marginal benefit over the trivial always-deterministic baseline (Appendix~\\ref{sec:threshold-routing}).\n\n\\subsection{Router Training: Inconclusive Results}\n\\label{sec:router-diagnostic}\n\nA Qwen3 LoRA router (0.6B--4B; Appendix~\\ref{app:router-details}) trained on counterfactual labels shows flat step-level balanced accuracy ($56$--$59\\%$) across all model scales; episode-level evaluation yields $47.1 \\pm 2.2\\%$, below majority-vote.\\footnote{Consistent with noisy-label bounds~\\citep{natarajan2013learning}: ${\\sim}$88\\% of step-level labels are uninformative with 90.5\\%/3.7\\% class imbalance (Appendix~\\ref{app:seed-robustness}).} Leave-one-task-out degrades to chance ($49.2\\%$), suggesting signal is a per-task-type constant rather than a learnable function of step-level observations. Deployed end-to-end, the best router (4B) scores $-10.70$, not exceeding always-deterministic ($-9.47$); this negative result is consistent with the death-dominance finding, as death avoidance cannot be predicted from pre-episode features when it depends on multi-step trajectory dynamics. Additional ablations (capacity scaling, generative routing, reasoning depth) are in Appendix~\\ref{app:ablations}.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nStrategy & Score & 95\\% CI & Death \\% \\\\\n\\midrule\nAlways-Internal & $-39.07$ & [$-46.40$, $-32.27$] & 42.9 \\\\\nAlways-Deterministic & $-9.47$ & [$-14.71$, $-4.29$] & 16.3 \\\\\nRandom & $-22.38$ & [$-28.67$, $-15.75$] & 27.8 \\\\\nOracle & $-6.58$ & [$-11.54$, $-1.70$] & 14.3 \\\\\n\\midrule\nTrained Router$^\\dagger$ & $-10.70$ & [$-16.33$, $-5.27$] & 17.6 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Episode-weighted mean scores on ScienceWorld (11 task types, 245 episodes). $\\dagger$\\,Single seed (42); see Appendix~\\ref{app:seed-robustness} for 8-seed robustness.}\n\\label{tab:baselines}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/signal_reversal.pdf}\n\\vspace{-2mm}\n\\caption{Cross-environment label distributions. ScienceWorld and ALFWorld both favor deterministic via different mechanisms (death avoidance vs.\\ information asymmetry); MATH shows no routing signal.}\n\\label{fig:signal-reversal}\n\\end{figure}\n",
      "numLines": 177,
      "startLine": 1,
      "totalLines": 177
    }
  },
  "sourceToolAssistantUUID": "1bbba60a-152d-4035-8def-331a8b0371b6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-25T15:16:41.093Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MtmqhAa4Ueqmbmk9yy7AHF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f9d61043-03ed-42a0-a7a1-96794ef4e5e4",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "a9e645a5-c054-4704-a228-0feac3549475",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 32 · 2026-05-25T15:16:41.098Z_

<details><summary>↩ Tool result · `toolu_01MtmqhAa4Ueqmbmk9yy7AHF`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Signal granularity and router failure.}
5	The router diagnostic (\S\ref{sec:router-diagnostic}) reveals a structural mismatch: death avoidance is a task-type-level binary property, but step-level features correlate weakly because death risk depends on multi-step trajectories. Six router variants (0.6B--4B) converge on near-chance balanced accuracy ($56$--$59\%$), and leave-one-task-out evaluation degrades to $49.2\%$, suggesting the router captures only task-type identity.
6	$10{\times}$ scaling to two 70B-class models fails to eliminate death dominance (DAF${}=92.4$--$101.0\%$), and Reflexion yields DAF${}>100\%$. Cross-model death-rate stability ($31$--$49\%$ across five models) provides evidence that death vulnerability is a task-environment property, suggesting routing in death-dominated environments is better addressed through action-space constraints (Appendix~\ref{app:grounding-ablation}) than learned step-level policies.
7	
8	\paragraph{Failure mechanism.}
9	All 105 internal-strategy deaths trace to a single action pattern: \texttt{focus on [object]}, ScienceWorld's answer-submission command. The LLM agent systematically misuses it as a general interaction command, applying it to irrelevant targets (rooms, doors, inventory items) and triggering the $-100$ penalty. Within death episodes, both strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$); the internal strategy's higher death count reflects how often it enters catastrophic states, not different action selection within those states. Action-space filtering---blocking \texttt{focus on} during exploration---reduces death rate by 19~pp with zero leaks (Appendix~\ref{app:grounding-ablation}), confirming that the behavior is a shallow pattern rather than a deliberate strategy.
10	
11	\paragraph{Oracle degeneracy and practical implications.}
12	Always-deterministic matches 96.3\% of oracle decisions (\S\ref{sec:baselines}), capping routing's marginal value at 2.89 points---an \emph{oracle degeneracy} where perfect per-episode foresight provides negligible benefit over a trivial baseline, because $\Delta_{\text{nd}} = 2.84$ (9.6\% of total gap).
13	For practitioners, the framework provides a lightweight diagnostic: a ${\sim}$50-episode pilot collecting paired pure-strategy outcomes suffices to compute the death-label fraction $f_{\text{death}}$ and assess whether learned routing adds value. Retrospective validation correctly classifies all four conditions in this paper (Appendix~\ref{app:decision-framework}). ALFWorld (DAF${=}0\%$) shows the framework diagnoses qualitatively different mechanisms---there, routing signal stems entirely from information asymmetry, indicating a learned router may add value.
14	
15	\paragraph{Scope and applicability conditions.}
16	The decomposition requires: (i)~binary catastrophic failures with fixed penalty, (ii)~asymmetric failure rates, and (iii)~$P \gg \Delta_\text{nd}$. ScienceWorld satisfies all three; MATH and ALFWorld lack the first. Graded penalties, stochastic severity, or symmetric failure rates would require DAF extensions. Targeted safety interventions---such as action-space filtering or grounding feedback---may outperform general-purpose routing in death-dominated settings, shifting the problem from ``which computation mode?'' to ``how to prevent catastrophic actions.''
17	
18	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a9e645a5-c054-4704-a228-0feac3549475",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "f25b6d59-18e9-4bc5-838d-5d2addee7fe4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Signal granularity and router failure.}\nThe router diagnostic (\\S\\ref{sec:router-diagnostic}) reveals a structural mismatch: death avoidance is a task-type-level binary property, but step-level features correlate weakly because death risk depends on multi-step trajectories. Six router variants (0.6B--4B) converge on near-chance balanced accuracy ($56$--$59\\%$), and leave-one-task-out evaluation degrades to $49.2\\%$, suggesting the router captures only task-type identity.\n$10{\\times}$ scaling to two 70B-class models fails to eliminate death dominance (DAF${}=92.4$--$101.0\\%$), and Reflexion yields DAF${}>100\\%$. Cross-model death-rate stability ($31$--$49\\%$ across five models) provides evidence that death vulnerability is a task-environment property, suggesting routing in death-dominated environments is better addressed through action-space constraints (Appendix~\\ref{app:grounding-ablation}) than learned step-level policies.\n\n\\paragraph{Failure mechanism.}\nAll 105 internal-strategy deaths trace to a single action pattern: \\texttt{focus on [object]}, ScienceWorld's answer-submission command. The LLM agent systematically misuses it as a general interaction command, applying it to irrelevant targets (rooms, doors, inventory items) and triggering the $-100$ penalty. Within death episodes, both strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$); the internal strategy's higher death count reflects how often it enters catastrophic states, not different action selection within those states. Action-space filtering---blocking \\texttt{focus on} during exploration---reduces death rate by 19~pp with zero leaks (Appendix~\\ref{app:grounding-ablation}), confirming that the behavior is a shallow pattern rather than a deliberate strategy.\n\n\\paragraph{Oracle degeneracy and practical implications.}\nAlways-deterministic matches 96.3\\% of oracle decisions (\\S\\ref{sec:baselines}), capping routing's marginal value at 2.89 points---an \\emph{oracle degeneracy} where perfect per-episode foresight provides negligible benefit over a trivial baseline, because $\\Delta_{\\text{nd}} = 2.84$ (9.6\\% of total gap).\nFor practitioners, the framework provides a lightweight diagnostic: a ${\\sim}$50-episode pilot collecting paired pure-strategy outcomes suffices to compute the death-label fraction $f_{\\text{death}}$ and assess whether learned routing adds value. Retrospective validation correctly classifies all four conditions in this paper (Appendix~\\ref{app:decision-framework}). ALFWorld (DAF${=}0\\%$) shows the framework diagnoses qualitatively different mechanisms---there, routing signal stems entirely from information asymmetry, indicating a learned router may add value.\n\n\\paragraph{Scope and applicability conditions.}\nThe decomposition requires: (i)~binary catastrophic failures with fixed penalty, (ii)~asymmetric failure rates, and (iii)~$P \\gg \\Delta_\\text{nd}$. ScienceWorld satisfies all three; MATH and ALFWorld lack the first. Graded penalties, stochastic severity, or symmetric failure rates would require DAF extensions. Targeted safety interventions---such as action-space filtering or grounding feedback---may outperform general-purpose routing in death-dominated settings, shifting the problem from ``which computation mode?'' to ``how to prevent catastrophic actions.''\n\n",
      "numLines": 18,
      "startLine": 1,
      "totalLines": 18
    }
  },
  "sourceToolAssistantUUID": "a9e645a5-c054-4704-a228-0feac3549475",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-25T15:16:41.571Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NgVSkuVTnG4WRvYoXW5XTW`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f25b6d59-18e9-4bc5-838d-5d2addee7fe4",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "ba1e5e96-8225-4a7e-8fcf-625a8eee0e5c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 34 · 2026-05-25T15:16:41.576Z_

<details><summary>↩ Tool result · `toolu_01NgVSkuVTnG4WRvYoXW5XTW`</summary>

```text
1	\section{Conclusion}
2	
3	Our episode-level counterfactual framework reveals that routing signal in ScienceWorld is dominated by a single mechanism: 78.9\% of non-tie labels trace to death asymmetry, a finding stable across three model families and two 70B-class models (DAF $92$--$101\%$). When routing signal collapses to catastrophic-failure avoidance, always-deterministic approaches oracle performance, and learned step-level routing offers limited additional value. Future work should validate this pattern in other catastrophic-failure environments and explore targeted episode collection to resolve the router's inconclusive result.
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ba1e5e96-8225-4a7e-8fcf-625a8eee0e5c",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "da633466-817b-445f-9d58-3e1a9479508a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\nOur episode-level counterfactual framework reveals that routing signal in ScienceWorld is dominated by a single mechanism: 78.9\\% of non-tie labels trace to death asymmetry, a finding stable across three model families and two 70B-class models (DAF $92$--$101\\%$). When routing signal collapses to catastrophic-failure avoidance, always-deterministic approaches oracle performance, and learned step-level routing offers limited additional value. Future work should validate this pattern in other catastrophic-failure environments and explore targeted episode collection to resolve the router's inconclusive result.\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  },
  "sourceToolAssistantUUID": "ba1e5e96-8225-4a7e-8fcf-625a8eee0e5c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-25T15:16:42.035Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NqzNsS4SovPAM3gn9Df63m`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "da633466-817b-445f-9d58-3e1a9479508a",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "188795a4-3eda-4a9a-acd5-4b9319c5bd1d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 36 · 2026-05-25T15:16:42.309Z_

<details><summary>↩ Tool result · `toolu_01NqzNsS4SovPAM3gn9Df63m`</summary>

```text
1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{graphicx}
11	\graphicspath{{figures/}}
12	\usepackage{booktabs}
13	\usepackage{amsmath}
14	\usepackage{amssymb}
15	\usepackage{algorithm}
16	\usepackage{algorithmic}
17	\usepackage{caption}
18	\usepackage{tcolorbox}
19	\tcbuselibrary{listings,breakable}
20	
21	\renewcommand{\topfraction}{0.9}
22	\renewcommand{\dbltopfraction}{0.9}
23	\renewcommand{\bottomfraction}{0.8}
24	\renewcommand{\textfraction}{0.1}
25	
26	\hypersetup{pdfauthor={},pdftitle={}}
27	
28	\title{Death Avoidance as the Dominant Routing Signal:\\A Counterfactual Analysis on ScienceWorld}
29	
30	\author{Anonymous}
31	
32	\begin{document}
33	\maketitle
34	
35	\input{abstract}
36	\input{introduction}
37	\input{related_work}
38	\input{method}
39	\input{experiments}
40	\input{discussion}
41	\input{conclusion}
42	
43	\section*{Limitations}
44	Full quantitative validation (DAF, label fractions) is specific to ScienceWorld; MATH and ALFWorld serve as boundary probes, not comprehensive cross-environment validation. DAF depends on a fixed death penalty ($P{=}100$); environments with graded or stochastic failure severity would require extensions (Appendix~\ref{app:penalty}). The internal baseline uses single-pass ReAct~\citep{react-2023}; more aggressive self-correction (e.g., Tree-of-Thought) may further reduce death rates and alter the signal composition. With $K{=}11$ task-type clusters, cluster bootstrap yields wider CIs; wild cluster bootstrap ($p < 0.001$; Appendix~\ref{app:wild-cluster}) and 100\% directional consistency across all 28 death-prone tasks provide partial mitigation.
45	
46	\bibliography{references}
47	
48	\appendix
49	
50	\noindent\textbf{Appendix Overview.}
51	\hyperref[app:sci]{A.~Signal Concentration Index} $\cdot$
52	\hyperref[app:labeling]{B.~Labeling Quality Audit} $\cdot$
53	\hyperref[app:per-task]{C.~Per-Task Decomposition} $\cdot$
54	\hyperref[app:correlation]{D.~Correlation Robustness} $\cdot$
55	\hyperref[app:wild-cluster]{E.~Cluster Bootstrap Sensitivity} $\cdot$
56	\hyperref[app:per-task-ci]{F.~Per-Task CIs} $\cdot$
57	\hyperref[app:loto-daf]{G.~Leave-One-Task-Out DAF} $\cdot$
58	\hyperref[app:dose-response]{H.~Dose-Response Breakdown} $\cdot$
59	\hyperref[app:router-details]{I.~Router Training Details} $\cdot$
60	\hyperref[app:seed-robustness]{J.~Seed Robustness} $\cdot$
61	\hyperref[app:penalty]{K.~Penalty Sensitivity} $\cdot$
62	\hyperref[app:cross-env-details]{L.~Cross-Environment Details} $\cdot$
63	\hyperref[app:cross-model]{M.~Cross-Model Verification} $\cdot$
64	\hyperref[app:failure-modes]{N.~Failure Mode Analysis} $\cdot$
65	\hyperref[app:grounding-ablation]{O.~Grounding Ablation} $\cdot$
66	\hyperref[app:ablations]{P.~Ablation Studies} $\cdot$
67	\hyperref[sec:threshold-routing]{Q.~Threshold Routing} $\cdot$
68	\hyperref[app:decision-framework]{R.~Decision Framework} $\cdot$
69	\hyperref[app:extended-validation]{S.~Extended Validation} $\cdot$
70	\hyperref[app:prompt-templates]{T.~Agent Prompt Templates} $\cdot$
71	\hyperref[app:non-death-case-study]{U.~Non-Death Episode Case Study}
72	
73	\section{Signal Concentration Index}
74	\label{app:sci}
75	
76	Let $K$ denote the number of task types and $c_k$ the contribution of task type $k$ to the aggregate routing signal, defined as the fraction of total death-rate differential attributable to task $k$:
77	\begin{equation}
78	    c_k = \frac{n_k \cdot \delta_k}{\sum_{j=1}^{K} n_j \cdot \delta_j}
79	\end{equation}
80	where $n_k$ is the number of episodes and $\delta_k = d_k^{\tt int} - d_k^{\tt det}$ is the per-task death-rate differential. The SCI is the Gini coefficient over $\{c_1, \ldots, c_K\}$:
81	\begin{equation}
82	    \text{SCI} = \frac{\sum_{i=1}^K \sum_{j=1}^K |c_i - c_j|}{2K \sum_{k=1}^K c_k}
83	\end{equation}
84	
85	\section{Labeling Quality Audit}
86	\label{app:labeling}
87	
88	Note that episode-level labels are used to evaluate step-level predictions, introducing a granularity mismatch rather than independent validation. A potential concern is oracle circularity: whether episode-level labels reflect tie-breaking artifacts rather than genuine computation mode differences. We audit all 245 labels. Of the 150 \texttt{no\_preference} labels (61.2\%), 115 (46.9\%) are both-alive ties and 35 (14.3\%) are both-dead, all excluded from router training. The remaining 95 training labels are entirely genuine: 75 from death asymmetry (70 deterministic-preferred, 5 internal-preferred) and 20 from score comparison with both strategies surviving (16 deterministic-preferred, 4 internal-preferred). Zero labels depend on tie-breaking. Retraining the router using only death-asymmetry labels yields step-level balanced accuracy of 57.3\%, within 1$\sigma$ of the full-label retrain (57.6 $\pm$ 0.5\%, step-level Trainer evaluation); score-comparison labels contribute negligible additional signal. (Step-level metrics are used here for the relative comparison; as shown in \S\ref{sec:router-diagnostic}, absolute generalization to new episodes is near chance.) The 97.4\% step-level tie rate (\S\ref{sec:collection}) further motivates episode-level over step-level labeling.
89	
90	\section{Per-Task Decomposition}
91	\label{app:per-task}
92	We use ScienceWorld v1.2.3~\citep{scienceworld-2022}.
93	We select 11 of ScienceWorld's 30 task types for analysis. Types are excluded when they were used for pipeline development (5 tasks, standard hold-out practice), are taxonomically redundant with a retained family representative (7 tasks), or exhibit near-zero task progress under both strategies (7 tasks, agent capability floor).\footnote{Excluded tasks exhibit even stronger death dominance than included tasks ($\Delta\text{DR} = +38.2$\,pp vs.\ $+28.7$\,pp; Table~\ref{tab:excluded-death}).}
94	
95	\paragraph{Task selection and anti-cherry-picking.}
96	Eighteen of the 19 excluded task types (95\%) exhibit death-asymmetric patterns (Table~\ref{tab:excluded-death}): internal-reasoning death rates range from 40\% to 60\% (mean 53.9\%), while deterministic death rates range from 0\% to 40\% (mean 15.8\%), yielding a mean death-rate differential of $+38.2$\,pp, exceeding the $+28.7$\,pp for included tasks. The included subset is thus \emph{less} death-asymmetric than the excluded subset, the opposite of what a cherry-picking hypothesis would predict. The sole exception is \texttt{grow-plant}, an intrinsically safe task with zero deaths under both strategies, paralleling \texttt{find-non-living-thing} in the included set. The 19 excluded tasks fall into three independently motivated categories: five used during pipeline development (standard hold-out practice), seven taxonomically redundant with included family representatives (deduplication), and seven where the 7B backbone achieves near-zero task progress regardless of strategy (agent capability floor). In no case was a task excluded because death dominance was absent. Exclusion is driven by absence of non-death routing signal ($\Delta_{\text{nd}} = 0$ for 53\% of excluded tasks) and standard deduplication practices. \texttt{find-non-living-thing} serves as an internal counterexample: zero deaths under both strategies yet included because it exhibits non-death routing signal ($\Delta_{\text{full}} = +9.58$ entirely from score differences), and deterministic is not always preferred (4 of 20 non-tie labels favor internal).
97	
98	\begin{table}[t]
99	\centering
100	\scriptsize
101	\setlength{\tabcolsep}{2pt}
102	\resizebox{\columnwidth}{!}{%
103	\begin{tabular}{@{}llrcccl@{}}
104	\toprule
105	Task & Grp & $n$ & D\%\textsubscript{int} & D\%\textsubscript{det} & $\Delta$DR & Excl.\ reason \\
106	\midrule
107	boil                          & A & 20 & 50 & 20 & $+30$ & dev set \\
108	change-state-of-matter        & A & 20 & 55 & 15 & $+40$ & dev set \\
109	chem-mix-paint-secondary      & A & 20 & 45 & 10 & $+35$ & dev set \\
110	grow-plant                    & A & 20 &  0 &  0 & $\phantom{+}0$  & dev set \\
111	melt                          & A & 20 & 55 & 15 & $+40$ & dev set \\
112	\midrule
113	chem-mix-paint-tertiary       & B &  5 & 40 & 20 & $+20$ & family redundancy \\
114	find-living-thing             & B &  5 & 60 & 20 & $+40$ & family redundancy \\
115	find-plant                    & B &  5 & 60 &  0 & $+60$ & family redundancy \\
116	inclined-friction-named       & B &  5 & 60 & 20 & $+40$ & family redundancy \\
117	inclined-friction-unnamed     & B &  5 & 60 &  0 & $+60$ & family redundancy \\
118	lifespan-shortest             & B &  5 & 60 & 40 & $+20$ & family redundancy \\
119	measure-melt-known            & B &  5 & 60 &  0 & $+60$ & family redundancy \\
120	\midrule
121	mendelian-known               & C &  5 & 60 & 20 & $+40$ & agent floor \\
122	mendelian-unknown             & C &  5 & 60 & 40 & $+20$ & agent floor \\
123	power-component               & C &  5 & 60 & 20 & $+40$ & agent floor \\
124	power-renewable               & C &  5 & 60 &  0 & $+60$ & agent floor \\
125	test-conductivity             & C &  5 & 60 & 20 & $+40$ & agent floor \\
126	test-conductivity-unknown     & C &  5 & 60 & 20 & $+40$ & agent floor \\
127	use-thermometer               & C &  5 & 60 & 20 & $+40$ & agent floor \\
128	\midrule
129	\textbf{Mean (19 excluded)}   &   &    & \textbf{53.9} & \textbf{15.8} & $\mathbf{+38.2}$ & \\
130	\textit{cf.\ included (11)}   &   &    & \textit{46.5} & \textit{17.8} & $\textit{+28.7}$ & \\
131	\bottomrule
132	\end{tabular}}%
133	\caption{Death-rate analysis of all 19 excluded task types. D\%: death rate (score $\leq -100$). $\Delta$DR = D\%\textsubscript{int} $-$ D\%\textsubscript{det}. 18 of 19 excluded tasks (95\%) exhibit positive death asymmetry ($\Delta$DR $\geq +20$\,pp). Exclusion groups: A = development set (excluded to prevent circular evaluation), B = taxonomically redundant with an included family representative, C = agent-floor tasks (backbone achieves near-zero progress regardless of strategy). The mean $\Delta$DR among excluded tasks ($+38.2$\,pp) exceeds that of included tasks ($+28.7$\,pp), confirming that task selection does not bias toward death-prone tasks. Group B--C estimates are based on $n{=}5$ prescreening episodes per task and should be interpreted as directional evidence rather than precise rate estimates.}
134	\label{tab:excluded-death}
135	\end{table}
136	
137	\section{Correlation Robustness}
138	\label{app:correlation}
139	
140	The Pearson $r = 0.9698$ reported in \S\ref{sec:death-decomp} is robust across multiple diagnostics. Spearman rank correlation is $\rho = 0.986$ ($p = 2.4 \times 10^{-8}$); the relationship is not driven by outliers or non-linearity. A nonparametric bootstrap (10{,}000 resamples) yields 95\% CI $[0.952, 0.995]$.
141	
142	\begin{table}[h]
143	\centering
144	\small
145	\begin{tabular}{@{}lr@{}}
146	\toprule
147	Task removed & $r_{\text{LOO}}$ \\
148	\midrule
149	id-life-stages-1       & 0.963 \\
150	lifespan-long          & 0.969 \\
151	lifespan-l-then-s      & 0.976 \\
152	inclined-plane         & 0.969 \\
153	freeze                 & 0.971 \\
154	meas-melt-point        & 0.972 \\
155	id-life-stages-2       & 0.972 \\
156	find-animal            & 0.970 \\
157	grow-fruit             & 0.973 \\
158	chem-mix               & 0.969 \\
159	find-non-living-thing  & 0.980 \\
160	\bottomrule
161	\end{tabular}
162	\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\ $\Delta_{\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}
163	\label{tab:loo}
164	\end{table}
165	
166	\section{Cluster Bootstrap Sensitivity Analysis}
167	\label{app:wild-cluster}
168	
169	With $K{=}11$ task-type clusters, cluster bootstrap falls well below the $K{\geq}20$--50 recommended for reliable inference \citep{cameron-2008,webb-2023}. The narrower CIs obtained reflect known small-sample bias toward underestimation of variance, not tighter inference.
170	
171	Episodes within the same task type share environment dynamics, raising the concern that the effective sample size is closer to $K$ (task types) than $N$ (episodes). We address this with cluster-robust inference treating each task type as a cluster ($K{=}11$, all 11 included task types, 245 episodes).
172	
173	\begin{table}[h]
174	\centering
175	\small
176	\resizebox{\columnwidth}{!}{%
177	\begin{tabular}{@{}lcc@{}}
178	\toprule
179	Method & $p$-value & 95\% CI \\
180	\midrule
181	Cluster-robust $t$-test ($t{=}10.0$, df$=$10) & $< 0.001$ & $[0.73, 1.00]$ \\
182	Wild cluster bootstrap ($B{=}9{,}999$) & $< 0.001$ & $[0.73, 1.00]$ \\
183	Exact permutation ($2{,}048$ perms) & $0.002$ & --- \\
184	Sign test & $< 0.001$ & --- \\
185	\bottomrule
186	\end{tabular}}%
187	\caption{Cluster-level tests of death-rate asymmetry ($K{=}11$ task clusters, 245 episodes). 10 of 11 clusters show internal DR $>$ deterministic DR; the sole exception (\texttt{find-non-living-thing}) has zero deaths under both strategies. Cohen's $d = 3.02$. The exact permutation $p = 0.002$ ($4/2{,}048$) reflects the near-unanimous directional consistency.}
188	\label{tab:wild-cluster}
189	\end{table}
190	
191	\noindent All methods confirm significance with $p < 0.01$, and the 95\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.
192	
193	We retain this analysis for transparency; readers should rely on the non-clustered episode-level bootstrap (\S\ref{sec:death-decomp}) as the primary inference.
194	
195	\section{Per-Task Death Rate Confidence Intervals}
196	\label{app:per-task-ci}
197	
198	We compute bootstrap 95\% CIs for the death-rate differential ($\Delta\text{DR} = \text{DR}_{\text{int}} - \text{DR}_{\text{det}}$) for all 30 ScienceWorld task types. Of 30 tasks, 28 are death-prone (at least one death under either strategy); the remaining 2 (\texttt{grow-plant}, \texttt{find-non-living-thing}) have zero deaths under both strategies.
199	
200	Across all 28 death-prone tasks, internal DR exceeds deterministic DR without exception (100\% directional consistency). The pooled death-rate differential is $+37.3\%$ (95\% CI: $[29.7\%, 44.4\%]$). Fifteen of 28 tasks are individually significant (CI excludes zero); the 13 non-significant tasks all have $n{=}5$ prescreening episodes, where statistical power is insufficient to detect even large effects (e.g., a task with $\Delta\text{DR} = +40$\,pp at $n{=}5$ has a CI of $\pm 43$\,pp). The universal directional consistency, combined with the pooled significance, confirms that death asymmetry is not driven by a subset of outlier tasks.
201	
202	\section{Leave-One-Task-Out DAF Sensitivity}
203	\label{app:loto-daf}
204	
205	Table~\ref{tab:loto-daf} (main text, \S\ref{sec:death-decomp}) reports the full leave-one-task-out DAF sensitivity analysis.
206	
207	\section{Per-Task Dose-Response Breakdown}
208	\label{app:dose-response}
209	
210	Table~\ref{tab:dose-response-detail} reports per-task death rates for Reflexion at $N{=}3$, 4, and 5 on the 10 death-prone tasks ($n{=}20$ episodes per task). Per-task variance is high (up to 25\,pp range for \texttt{measure-melting-point}), but the aggregate smooths to a 2.5\,pp band, confirming that the stabilization conclusion is robust at the aggregate level despite task-level noise. \texttt{freeze} is consistently the hardest task (50--60\% DR across all $N$).
211	
212	\paragraph{Statistical power.} With $n{=}200$ paired episodes, the minimum detectable effect (MDE) is ${\sim}8$~pp ($\alpha = 0.05$, 80\% power). The key $N{=}1{\to}3$ decline ($-13.5$~pp) exceeds this threshold and is well-powered; the stabilization claim ($N{=}3{\to}5$, $+1.0$~pp) is also supported, since a ${\geq}8$~pp improvement would be detected if present.
213	
214	\begin{table}[h]
215	\centering
216	\small
217	\caption{Per-task death rates (\%) for Reflexion at $N{=}3$, 4, 5 on 10 death-prone tasks ($n{=}20$ per task). Aggregate death rates confirm stabilization at $N \geq 3$ (range: $34.0$--$36.5\%$).}
218	\label{tab:dose-response-detail}
219	\begin{tabular}{@{}lrrr@{}}
220	\toprule
221	Task & $N{=}3$ & $N{=}4$ & $N{=}5$ \\
222	\midrule
223	chemistry-mix & 25.0 & 35.0 & 20.0 \\
224	find-animal & 45.0 & 30.0 & 45.0 \\
225	freeze & 50.0 & 50.0 & 60.0 \\
226	grow-fruit & 30.0 & 25.0 & 25.0 \\
227	identify-life-stages-1 & 35.0 & 35.0 & 35.0 \\
228	identify-life-stages-2 & 25.0 & 25.0 & 30.0 \\
229	inclined-plane-angle & 20.0 & 30.0 & 35.0 \\
230	lifespan-longest & 45.0 & 40.0 & 40.0 \\
231	lifespan-long+short & 30.0 & 45.0 & 35.0 \\
232	measure-melting-pt & 35.0 & 50.0 & 25.0 \\
233	\midrule
234	\textbf{Aggregate} & \textbf{34.0} & \textbf{36.5} & \textbf{35.0} \\
235	\bottomrule
236	\end{tabular}
237	\end{table}
238	
239	\section{Router Training Details}
240	\label{app:router-details}
241	
242	We use Qwen3-1.7B for the router to avoid circular dependency with the Qwen2.5-7B data-generating model.
243	
244	With gradient accumulation of 1 (effective batch size 4), routing performance is highly sensitive to the evaluation split; this suggests overfitting to specific train/validation partition boundaries. With gradient accumulation of 8 (effective batch size 32), step-level performance stabilizes across splits (${\sim}54\%$ balanced accuracy). All reported results use gradient accumulation 8.
245	
246	Under step-level evaluation with a fixed data split, cross-seed balanced accuracy ranges from 52.7\% to 58.1\%, but internal recall varies from 51.5\% to 81.8\%, which reflects threshold sensitivity. However, episode-level evaluation reveals that this apparent discrimination does not generalize: balanced accuracy drops to $47.1 \pm 2.2\%$ across 8 cross-split seeds (Appendix~\ref{app:seed-robustness}). Deployed end-to-end, the trained router allocates 97.0\% of episodes to deterministic computation with 17.6\% death rate, and misrouting cost (death from internally-routed episodes) exceeds the benefit of correctly routing rare internal-preferred cases.
247	
248	\paragraph{Evaluation methods.} All results use \emph{generation-based evaluation}: the model generates a routing label as text (\texttt{enable\_thinking=False}), parsed for classification. We evaluate at two granularities: \emph{step-level} (steps from the same episode may appear in both train and validation sets) and \emph{episode-level} (entire episodes held out). Step-level accuracy ($54.1 \pm 5.4\%$) exceeds chance (the router captures some signal), but episode-level accuracy ($47.1 \pm 2.2\%$, below chance) shows this does not generalize to unseen episodes. Paraphrase-based text augmentation (Appendix~\ref{app:seed-robustness}) provides no improvement; real-data scaling remains open. Always-deterministic is trivially near-optimal given DAF $= 90.4\%$. The main text (\S\ref{sec:router-diagnostic}) reports controlled 4-seed results at three scales; the model-size ablation (Appendix~\ref{app:ablations}) provides further detail.
249	
250	\begin{table}[h]
251	\centering
252	\small
253	\resizebox{\columnwidth}{!}{%
254	\begin{tabular}{@{}lcc@{}}
255	\toprule
256	Hyperparameter & Classification Head & Implicit Router \\
257	\midrule
258	Base model & Qwen3-1.7B & Qwen3-1.7B \\
259	Architecture & Linear + LoRA & SFT + LoRA \\
260	LoRA $r$ / $\alpha$ & 16 / 32 & 16 / 32 \\
261	Learning rate & 2e-5 & 2e-4 \\
262	Optimizer & AdamW & AdamW \\
263	Epochs & 3 & 3 \\
264	Batch size (per device) & 4 & 4 \\
265	Gradient accumulation & 8 & 8 \\
266	Warmup ratio & 0.1 & 0.1 \\
267	Weight decay & 0.01 & 0.01 \\
268	Max sequence length & 512 & 512 \\
269	Seeds & \{42\} & \{42, 123, 456, 789\} \\
270	\bottomrule
271	\end{tabular}}
272	\caption{Router training hyperparameters. Both architectures use the same base model with LoRA adaptation. The classification head degenerates across all configurations; the implicit router results are reported as 4-seed mean$\pm$std.}
273	\label{tab:hyperparams}
274	\end{table}
275	
276	\paragraph{Agent inference parameters.}
277	For ScienceWorld, each agent step uses temperature $T{=}0.3$ and maximum generation length of 256 tokens, served via vLLM v0.21.0. Top-$p$ is left at the vLLM default of $1.0$ (no nucleus sampling). For MATH, the agent uses greedy decoding ($T{=}0.0$) with a maximum of 2{,}048 tokens per generation. For ALFWorld, we use $T{=}0.3$ with 256 maximum tokens. All three environments use Qwen2.5-7B-Instruct~\citep{qwen25-2024} as the backbone.
278	
279	\section{Seed Robustness}
280	\label{app:seed-robustness}
281	
282	\paragraph{Counterfactual collection seed.}
283	We re-collect all episodes with a different ScienceWorld environment seed (seed=123, $N{=}220$, 20 episodes per task type).
284	The replication yields DAF $= 89.7\%$ ($\Delta_\text{nd} = 2.83$, $\Delta_\text{full} = 27.47$),
285	within 0.73~pp of the primary estimate (seed=42, DAF $= 90.4\%$).
286	Label distributions are consistent: 67 deterministic-preferred / 7 internal-preferred / 146 no-preference
287	(primary: 86 / 9 / 150).
288	Death rates by strategy remain directionally aligned ($\text{DR}_\text{int} = 45.5\%$ vs.\ $42.9\%$; $\text{DR}_\text{det} = 20.9\%$ vs.\ $16.3\%$).
289	The seed=123 replication uses $N{=}220$ ($20$ episodes per task type);
290	the primary dataset's larger $N{=}245$ reflects 25 additional episodes across two task types (\texttt{find-non-living-thing}: $n{=}40$; \texttt{lifespan-longest-lived}: $n{=}25$; all others: $n{=}20$).
291	
292	\paragraph{Router training seed.}
293	We assess router generalization at two evaluation granularities: \emph{step-level}, where steps from the same episode may appear in both train and validation sets, and \emph{episode-level}, where entire episodes are held out. Both use cross-split evaluation (seeds $\{42, \ldots, 49\}$, 8 seeds total), where the data partition and training seed both vary. Table~\ref{tab:seed-robustness} reports per-seed results.
294	
295	\begin{table}[h]
296	\centering
297	\small
298	\begin{tabular}{@{}llcc@{}}
299	\toprule
300	Eval.\ Granularity & Seed & Bal.\ Acc.\ (\%) \\
301	\midrule
302	Step-level & 42 & 57.06 \\
303	(same-episode & 43 & 63.99 \\
304	leakage) & 44 & 55.43 \\
305	 & 45 & 56.14 \\
306	 & 46 & 55.45 \\
307	 & 47 & 50.08 \\
308	 & 48 & 48.03 \\
309	 & 49 & 59.30 \\
310	\cmidrule{2-3}
311	 & Mean$\pm$std & $54.1 \pm 5.4$ \\
312	\midrule
313	Episode-level & 42 & 48.1 \\
314	(held-out & 43 & 47.9 \\
315	episodes) & 44 & 49.6 \\
316	 & 45 & 49.4 \\
317	 & 46 & 48.5 \\
318	 & 47 & 43.1 \\
319	 & 48 & 45.4 \\
320	 & 49 & 44.8 \\
321	\cmidrule{2-3}
322	 & Mean$\pm$std & $47.1 \pm 2.2$ \\
323	\midrule
324	\multicolumn{2}{@{}l}{Always-det (= majority-vote)} & 50.0 \\
325	\bottomrule
326	\end{tabular}
327	\caption{Per-seed router performance under cross-split evaluation (8 seeds, generation-based, \texttt{enable\_thinking=False}). Step-level evaluation allows steps from the same episode in both train and validation sets (same-episode leakage). Episode-level evaluation holds out entire episodes; the resulting $47.1 \pm 2.2\%$ is below the 50\% chance baseline. A text augmentation ablation (Table~\ref{tab:text-augmentation}) confirms this failure persists under the current data distribution and augmentation regime.}
328	\label{tab:seed-robustness}
329	\end{table}
330	
331	The contrast between step-level ($54.1 \pm 5.4\%$) and episode-level ($47.1 \pm 2.2\%$) evaluation reveals a generalization gap: the step-level signal likely reflects memorization of episode-specific context (enabled by same-episode leakage) rather than extraction of generalizable routing features. At episode level, the router performs below chance across all 8 seeds (range: 43.1\%--49.6\%). Paraphrase-based text augmentation (Table~\ref{tab:text-augmentation}) from 25\% to 800\% ($32{\times}$ range) provides no improvement, converging to the always-deterministic baseline ($50\%$). Paraphrase augmentation inflates the majority class without generating novel routing patterns; genuine episode-level scaling (collecting more counterfactual pairs) remains an open question. With DAF $= 90.4\%$ and all task types deterministic-majority (86:9 label ratio), always-deterministic trivially solves the episode-level routing problem, leaving the step-level router with no exploitable signal under current architectures.
332	
333	\paragraph{Text augmentation ablation.} To test whether the episode-level generalization failure stems from data scarcity, we vary training set size from 25\% to 800\% of the original via paraphrase-based text augmentation (synonym substitution + template variation on step observations), holding the episode-level validation set fixed. This tests augmentation-based scaling, not genuine episode-level scaling (which would require new counterfactual collections). Table~\ref{tab:text-augmentation} reports the results.
334	
335	\begin{table}[h]
336	\centering
337	\small
338	\begin{tabular}{@{}rccc@{}}
339	\toprule
340	Scale & Samples & Det\% & Ep.\ Bal.\ Acc.\ (\%) \\
341	\midrule
342	25\% & 433 & ${\sim}90$ & $49.5 \pm 0.3$ \\
343	50\% & 867 & ${\sim}90$ & $51.5$ \\
344	100\% & 1{,}735 & 89.6 & $49.9 \pm 0.1$ \\
345	200\% & 3{,}470 & 94.2 & $50.0 \pm 0.0$ \\
346	800\% & 13{,}880 & ${\sim}97.7$ & $51.0 \pm 1.1$ \\
347	\midrule
348	Always-det & --- & --- & 50.0 \\
349	\bottomrule
350	\end{tabular}
351	\caption{Text augmentation ablation: episode-level balanced accuracy across training set sizes (25\%--800\% of original via paraphrase, $32{\times}$ range). Internal recall $= 0.0$ at all scales (complete majority-class collapse). Det\%: fraction of deterministic-preferred labels in training data. The 50\% scale is a single seed; all others report mean$\pm$std across seeds.}
352	\label{tab:text-augmentation}
353	\end{table}
354	
355	All scales hover at ${\sim}50\%$ episode-level balanced accuracy (equivalent to the always-deterministic baseline), with no monotonic improvement as data increases. Augmentation-based scaling provides no improvement at any scale; however, episode-level minority-class diversity remains a potential confound that cannot be resolved without collecting more internal-preferred episodes. The ground-truth internal-preferred rate (9/245 $= 3.7\%$) means collecting 50 internal-preferred episodes would require approximately 1{,}350 paired episodes at current environment dynamics, a $5.5{\times}$ expansion with diminishing return on a $9.6\%$ signal. The failure points to a limitation of the current data distribution: when DAF $= 90.4\%$ and all task types are deterministic-majority (86:9 label ratio), the episode-level routing problem is trivially solved by always choosing deterministic, and the step-level router finds no exploitable signal under the current architecture and data regime.
356	
357	Augmentation disproportionately increases the majority (deterministic) class: Det\% rises from 89.6\% at 100\% to 94.2\% at 200\% and ${\sim}97.7\%$ at 800\%. However, the complete collapse to majority-class prediction (internal recall $= 0.0$) occurs even at the smallest unaugmented scale (25\%, ${\sim}90\%$ det); this is not an augmentation artifact. Balanced accuracy corrects for class imbalance by averaging per-class recall, so the metric itself is not biased by the skew.
358	
359	Decomposition metrics are stable under bootstrap resampling ($B{=}10{,}000$ resamples of the 245-episode dataset): DAF $= 90.4\% \pm 4.2\%$ (95\% CI $[81.3\%, 99.1\%]$); Pearson $r = 0.975 \pm 0.011$ (95\% CI $[0.952, 0.995]$). The death avoidance dominance finding is robust to both resampling and split perturbation.
360	
361	\paragraph{Per-task-type evaluation breakdown.} To test whether the router learns transferable routing strategies or merely task-type classification, we evaluate existing checkpoints (8 seeds) separately on each of the 11 task types. Of the 11 task types, 7 have \emph{all-deterministic} labels (no internal-preferred episodes exist), making balanced accuracy undefined; the router has nothing to learn beyond the trivial always-deterministic default. For the remaining 4 task types where both classes are present, balanced accuracy ranges from 50.0\% to 73.0\%, but this apparent signal does not indicate cross-task-type routing transfer: the router is effectively classifying task types (which correlate with death risk) rather than extracting a generalizable routing strategy. This complements the text augmentation ablation: routing signal does not transfer across task types because the signal \emph{is} the task type, i.e., whether a given task carries death risk. The 4B capacity scaling result (Appendix~\ref{app:ablations}) suggests capacity is one factor, but even 4B's $59.0\%$ episode-level accuracy does not demonstrate cross-task-type transfer.
362	
363	\section{Penalty Sensitivity Analysis}
364	\label{app:penalty}
365	
366	Table~\ref{tab:penalty-sensitivity} (main text, \S\ref{sec:daf}) reports DAF sensitivity across penalty magnitudes.
367	
368	The non-death score gap $\Delta_{\text{nd}} = 2.84$ is invariant across penalty levels; it depends only on surviving-episode performance, not on $P$. As $P$ increases, $\Delta_{\text{full}}$ grows ($16.33$ at $P{=}50$, $29.60$ at $P{=}100$, $56.13$ at $P{=}200$) while $\Delta_{\text{nd}}$ remains fixed, mechanically increasing DAF.
369	
370	\paragraph{Mechanism boundary: death specificity.}
371	The $r = 0.97$ correlation between per-task death-rate differential and $\Delta_{\text{full}}$ is specific to catastrophic death (score $= -100$). Broader failure definitions dissolve the correlation entirely: defining ``failure'' as any non-positive score ($T{=}0$) yields $r = -0.13$ ($p = 0.70$), because non-death episodes show near-zero performance differential between strategies ($\Delta_{\text{nd}} = 2.84$). Table~\ref{tab:penalty-correlation} quantifies this specificity across penalty magnitudes.
372	
373	\begin{table}[h]
374	\centering
375	\small
376	\begin{tabular}{@{}rccl@{}}
377	\toprule
378	$P$ & $r$ & $p$ & Sig.\ ($\alpha{=}0.05$) \\
379	\midrule
380	1 & $-0.44$ & $0.178$ & No \\
381	5 & $-0.29$ & $0.382$ & No \\
382	10 & $-0.08$ & $0.813$ & No \\
383	25 & $0.51$ & $0.108$ & No \\
384	50 & $0.86$ & $0.0006$ & Yes \\
385	100\textsuperscript{*} & $0.97$ & $8 \times 10^{-7}$ & Yes \\
386	200 & $0.99$ & $1 \times 10^{-9}$ & Yes \\
387	\bottomrule
388	\end{tabular}
389	\caption{Pearson $r$ between per-task death-rate differential and $\Delta_{\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \textsuperscript{*}Default ScienceWorld setting.}
390	\label{tab:penalty-correlation}
391	\end{table}
392	
393	This sharpens our central finding: death is not merely the dominant component of routing signal; it is effectively the \emph{only} component that generates differential routing signal in ScienceWorld. At low penalties, the death contribution is small and $\Delta_{\text{full}}$ reduces to $\Delta_{\text{nd}} \approx 2.84$, which is near-uniform across task types ($\text{mean non-death gap} = -1.19$ excluding the \texttt{find-non-living-thing} outlier); consequently, death-rate differential has no predictive power. As $P$ increases, the death term dominates $\Delta_{\text{full}}$, and the correlation sharpens because death rates \emph{are} the performance gap. The DAF values in Table~\ref{tab:penalty-sensitivity} increase monotonically with $P$, but this is a mathematical consequence of the decomposition ($\text{DAF} = \delta P / (\delta P + \Delta_{\text{nd}})$), not evidence of mechanism robustness.
394	
395	\section{Cross-Environment Details}
396	\label{app:cross-env-details}
397	
398	Table~\ref{tab:cross-env} summarizes the label distributions across all three environments (see also Figure~\ref{fig:signal-reversal} in \S\ref{sec:cross-env}).
399	
400	\begin{table}[h]
401	\centering
402	\small
403	\resizebox{\columnwidth}{!}{%
404	\begin{tabular}{@{}lccccc@{}}
405	\toprule
406	Environment & $N$ & Det\% & Int\% & NoPref\% & Death? \\
407	\midrule
408	ScienceWorld & 245 & 35.1 & 3.7 & 61.2 & Yes ($-100$) \\
409	MATH & 795 & 7.3 & 8.3 & 84.4 & No \\
410	ALFWorld & 135 & 25.9 & 1.5 & 72.6 & No\textsuperscript{$\dagger$} \\
411	\bottomrule
412	\end{tabular}}
413	\caption{Cross-environment label distribution. ``Deterministic'' denotes qualitatively different computation modes: ScienceWorld = oracle simulator with ground-truth state; MATH = Python code interpreter; ALFWorld = admissible-action enumeration. $\dagger$\,ALFWorld's deterministic advantage stems from information asymmetry, not death avoidance.}
414	\label{tab:cross-env}
415	\end{table}
416	
417	Table~\ref{tab:alfworld-pertask} provides the per-task-type breakdown for ALFWorld. Unlike ScienceWorld, ALFWorld has no death mechanism ($\delta = 0$, DAF $= 0\%$); the entire performance gap $\Delta_{\text{full}}$ reflects information asymmetry from admissible-action access. \texttt{pick\_and\_place} shows the strongest effect ($\Delta = 0.563$, 18 of 32 episodes det-preferred), while \texttt{pick\_two\_obj\_and\_place} shows the weakest ($\Delta = 0.087$), consistent with multi-object tasks requiring more sequential reasoning that admissible actions alone cannot resolve. Only \texttt{pick\_heat\_then\_place} has a 95\% CI crossing zero ($n{=}16$).
418	
419	\begin{table}[h]
420	\centering
421	\scriptsize
422	\setlength{\tabcolsep}{2.5pt}
423	\begin{tabular}{@{}lrcccc@{}}
424	\toprule
425	Task Type & $n$ & Succ\%\textsubscript{int} & Succ\%\textsubscript{det} & D / I / N & $\Delta_{\text{full}}$ \\
426	\midrule
427	pick\_and\_place       & 32 & 0.0  & 56.3 & 18 / 0 / 14 & $+0.563$ \\
428	look\_at\_obj\_in\_light & 13 & 15.4 & 38.5 & 3 / 0 / 10  & $+0.231$ \\
429	pick\_cool\_then\_place & 24 & 0.0  & 16.7 & 4 / 0 / 20  & $+0.167$ \\
430	pick\_clean\_then\_place & 27 & 3.7  & 18.5 & 5 / 1 / 21  & $+0.148$ \\
431	pick\_heat\_then\_place & 16 & 6.3  & 18.8 & 3 / 1 / 12  & $+0.125$ \\
432	pick\_two\_obj\_and\_place & 23 & 0.0 & 8.7  & 2 / 0 / 21  & $+0.087$ \\
433	\midrule
434	\textbf{All (6 types)} & \textbf{135} & \textbf{3.0} & \textbf{27.4} & \textbf{35 / 2 / 98} & $\mathbf{+0.244}$ \\
435	\bottomrule
436	\end{tabular}
437	\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\Delta_{\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\Delta_{\text{full}}$ descending.}
438	\label{tab:alfworld-pertask}
439	\end{table}
440	
441	\paragraph{MATH subset composition.}
442	The $N{=}795$ MATH problems span two categories from the MATH test set~\citep{math-2021} (Levels 4--5): Algebra (585, 73.6\%) and Counting \& Probability (210, 26.4\%). The category imbalance reflects the relative sizes in the original test set.
443	
444	\section{Cross-Model Verification}
445	\label{app:cross-model}
446	
447	We replicate the counterfactual analysis with Llama-3.1-8B-Instruct across all 11 task types ($N{=}220$ episode pairs, 20 per type; Table~\ref{tab:cross-model-detail}).
448	The internal strategy dies in $41.4\%$ of episodes versus $11.4\%$ for deterministic (death-rate differential $+30.0$~pp), with 83 deterministic-preferred, 3 internal-preferred (1.4\%, all death-asymmetry reversals), and 134 no-preference labels.
449	Both models exhibit nearly identical internal vulnerability (${\sim}$42\%: Qwen $42.9\%$, Llama $41.4\%$), confirming that death-prone failure is empirically dominated by the task environment rather than model-specific factors. The differential magnitude varies ($+26.5$~pp Qwen, $+30.0$~pp Llama) because deterministic strategy safety is model-dependent ($16.3\%$ vs.\ $11.4\%$), but directional consistency is 100\% (10/10 death-prone tasks in both models).
450	\texttt{identify-life-stages-1} shows cross-model precision matching ($55\%$/$10\%$/$+45$~pp in both models).
451	\texttt{find-non-living-thing} shows zero deaths in both models, consistent with its majority-class answer distribution.
452	
453	\begin{table}[h]
454	\centering
455	\small
456	\resizebox{\columnwidth}{!}{%
457	\begin{tabular}{@{}lrrrl@{}}
458	\toprule
459	Task & Int\% & Det\% & $\Delta$\,pp & D / I / N \\
460	\midrule
461	identify-life-stages-1 & 55 & 10 & +45 & 9 / 0 / 11 \\
462	freeze & 45 & 0 & +45 & 9 / 0 / 11 \\
463	grow-fruit & 45 & 5 & +40 & 8 / 0 / 12 \\
464	identify-life-stages-2 & 45 & 5 & +40 & 8 / 0 / 12 \\
465	measure-melting-point & 50 & 15 & +35 & 9 / 0 / 11 \\
466	lifespan-longest & 35 & 5 & +30 & 7 / 1 / 12 \\
467	lifespan-l-then-s & 50 & 20 & +30 & 6 / 0 / 14 \\
468	chemistry-mix & 45 & 20 & +25 & 5 / 0 / 15 \\
469	inclined-plane & 45 & 20 & +25 & 6 / 0 / 14 \\
470	find-animal & 40 & 25 & +15 & 6 / 2 / 12 \\
471	find-non-living-thing & 0 & 0 & 0 & 10 / 0 / 10 \\
472	\midrule
473	\textbf{Aggregate} & \textbf{41.4} & \textbf{11.4} & \textbf{+30.0} & \textbf{83 / 3 / 134} \\
474	\bottomrule
475	\end{tabular}}%
476	\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\Delta$ DR descending.}
477	\label{tab:cross-model-detail}
478	\end{table}
479	
480	\paragraph{Cross-model and cross-environment summary.}
481	Table~\ref{tab:cross-model-env} (main text, \S\ref{sec:cross-model}) consolidates replication results across model families and environments.
482	
483	\section{Failure Mode Analysis}
484	\label{app:failure-modes}
485	
486	All 105 internal-strategy deaths (100\%) are triggered by the same action pattern: \texttt{focus on [object]}. In ScienceWorld, \texttt{focus on} is the answer-submission action (equivalent to ``this is my final answer''); the LLM agent systematically misuses it as a general interaction or exploration command, and applies it to irrelevant targets (rooms, doors, inventory items). Each such execution submits an incorrect answer and triggers the $-100$ death penalty. Within death episodes, both strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$); the internal strategy's higher death count (105 vs.\ 40 for deterministic) reflects how often each strategy enters catastrophic states, not different action selection within those states.
487	
488	Manual inspection identifies four failure categories: (A) no task awareness, where the agent executes \texttt{focus on} without reading the task; (B) task-aware but lacking action grounding, where the agent correctly identifies the objective but cannot map it to valid action primitives; (D) genuine attempts with execution failure; and (E) initial progress wasted by early errors. Category B dominates: agents demonstrate task comprehension but systematically fail to translate it into correct ScienceWorld actions. This taxonomy was produced by a single annotator; no inter-annotator agreement was computed. The categories are intended as qualitative illustrations, not as formal labels with reliability guarantees.
489	\label{tab:death-taxonomy}
490	
491	\paragraph{Representative examples.}
492	\emph{Category A} (no task awareness): In a \texttt{chemistry-mix} episode, the agent immediately executes \texttt{focus on kitchen}, \texttt{focus on door}, \texttt{focus on inventory} without reading the task, dying on the first \texttt{focus on} call. \emph{Category B} (comprehension without grounding): In a \texttt{lifespan-longest-lived} episode, the agent correctly identifies that it must compare animal lifespans and reasons about which animal lives longest, but then executes \texttt{focus on oak tree} (a non-animal object in the room) instead of navigating to find the target animal, triggering death.
493	
494	\paragraph{Action distribution analysis.}
495	Figure~\ref{fig:death-action-dist} shows the action distribution in death versus non-death episodes for the internal strategy; both are dominated by \texttt{connect} actions, with \texttt{focus on} moderately more frequent in death episodes ($5.4\%$ vs.\ $3.4\%$). Crucially, Figure~\ref{fig:death-comparison} reveals that within death episodes, internal and deterministic strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$). The survival gap (105 vs.\ 40 deaths) therefore reflects how often each strategy enters catastrophic states, not how it behaves within those states. Among fatal \texttt{focus on} targets, \texttt{workshop} remains the most frequent (20.0\%), followed by \texttt{inventory} (17.1\%) and \texttt{kitchen} (10.5\%), indicating a systematic object bias rather than random exploration. Figure~\ref{fig:death-timeline} visualizes the temporal pattern: agents execute long sequences of \texttt{connect} actions before a terminal \texttt{focus on} triggers death, typically in the final 1--3 steps.
496	
497	\begin{figure}[h]
498	\centering
499	\includegraphics[width=\columnwidth]{figures/death_action_distribution.pdf}
500	\caption{Action distribution for the internal (LLM) strategy in death ($n{=}105$) vs.\ non-death ($n{=}140$) episodes. Left: full distribution (both dominated by \texttt{connect}). Right: non-\texttt{connect} actions zoomed. \texttt{focus on} is moderately more frequent in death episodes ($5.4\%$ vs.\ $3.4\%$), while non-death episodes show higher rates of observation and object interaction.}
501	\label{fig:death-action-dist}
502	\end{figure}
503	
504	% Figure moved to main text (\S\ref{sec:death-decomp})
505	
506	\begin{figure}[h]
507	\centering
508	\includegraphics[width=\columnwidth]{figures/death_action_comparison.pdf}
509	\caption{Non-\texttt{connect} action distribution comparison between internal (left) and deterministic (right) strategies. Within death episodes, both strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$); the internal strategy's higher death count (105 vs.\ 40) reflects more frequent entry into catastrophic states, not different action selection within those states.}
510	\label{fig:death-comparison}
511	\end{figure}
512	
513	\section{Grounding Ablation}
514	\label{app:grounding-ablation}
515	
516	We test whether directly intervening on the dominant death action (\texttt{focus on}) eliminates death vulnerability on the 10 death-prone tasks (baseline 48.0\%, $n{=}200$).
517	
518	\paragraph{Prompt warning.} Adding an explicit system prompt (``use \texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\% ($\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\texttt{identify-life-stages-1}: 35\%$\to$50\%; \texttt{identify-life-stages-2}: 25\%$\to$70\%), where explicit mention of the dangerous action may have increased its salience.
519	
520	\paragraph{Action-space filtering.} Blocking \texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\% ($\Delta = -19$~pp). The zero-passthrough rate suggests \texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.
521	
522	\paragraph{Per-task variation.} Under filtering, \texttt{identify-life-stages} and \texttt{inclined-plane} approach deterministic-level safety (${\sim}$15--20\% DR), while \texttt{chemistry-mix} and \texttt{find-animal} remain at 35--40\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \texttt{focus on} to incorrect objects.
523	
524	\paragraph{Post-ablation counterfactual decomposition.}
525	To test whether death dominance persists after grounding intervention, we run the full decomposition on matched episodes (183 episodes across 10 death-prone task types, paired by variation index).
526	Grounding reduces the internal death rate from 50.3\% to 35.0\% ($-15.3$\,pp), yet $\geq$93\% of disambiguating labels still arise from death asymmetry ($\Delta_\text{nd} \approx 0.09$, compared to $0.00$ at baseline).
527	Internal-preferred episodes increase from 5 to 23 (grounding helps internal strategy survive more often), but the routing signal remains death-driven rather than score-driven.
528	One task type (\texttt{identify-life-stages-2}, $n{=}10$) shows a paradoxical increase in death rate (50\%$\to$80\%); this outlier likely reflects the small sample size and task-specific prompt interference rather than a systematic effect.
529	
530	\section{Ablation Studies}
531	\label{app:ablations}
532	
533	\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\ref{tab:capacity}).
534	
535	\begin{table}[h]
536	\centering
537	\small
538	\begin{tabular}{@{}lcc@{}}
539	\toprule
540	Model & Step Bal.\ Acc.\ (\%) & Ep.\ Bal.\ Acc.\ (\%) \\
541	\midrule
542	Qwen3-0.6B & $56.4 \pm 3.5$ & $50.7 \pm 2.6$ \\
543	Qwen3-1.7B & $58.2 \pm 4.0$ & $43.1 \pm 1.0$ \\
544	Qwen3-4B & $59.2 \pm 3.5$ & $\mathbf{59.0 \pm 1.9}$ \\
545	\midrule
546	Always-det & 50.0 & 50.0 \\
547	\bottomrule
548	\end{tabular}
549	\caption{Capacity scaling: step-level and episode-level balanced accuracy (4 seeds, identical configuration across all scales). Step-level accuracy is flat ($56$--$59\%$, within seed variance). At episode level, only 4B breaks the random baseline ($59.0\%$, $p < 0.005$).}
550	\label{tab:capacity}
551	\end{table}
552	
553	Step-level balanced accuracy is flat across scales ($56$--$59\%$, within seed variance); step-level discrimination is not capacity-sensitive. At episode level, only 4B breaks the random baseline ($59.0 \pm 1.9\%$, $p < 0.005$); 0.6B and 1.7B remain at or below chance. The 1.7B model's below-chance episode-level accuracy ($43.1\%$) may reflect overfitting to spurious step-level correlations that anti-correlate with episode outcomes; without per-class confusion matrices at this scale, this remains a hypothesis. The dominant explanation across scales is that death avoidance constitutes a task-type-level binary signal that a step-level router cannot exploit efficiently.
554	
555	\paragraph{Generative router.} A generative routing model trained with explicit routing labels achieves balanced accuracy of 46.7\%, confirming that the routing bottleneck is signal-limited, not architecture-limited.
556	
557	\paragraph{Leave-one-task-type-out routing.} Under leave-one-task-type-out evaluation, blind routing collapses to always-deterministic (balanced accuracy 50.0\%); a keyword-based variant achieves 62.9\% only through task-identity leakage, not genuine routing signal. A guided router evaluated under the same protocol confirms this: without task-type identifiers it achieves chance accuracy (50.0\%), and leaking task names raises this to 62.9\%, confirming that the only learnable routing feature is task-type identity.
558	
559	\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\%, episode balanced accuracy 50.0\%, internal recall 0\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.
560	
561	\paragraph{Reasoning depth.} An ablation comparing chain-of-thought reasoning against direct-answer generation on 6 task types ($n{=}120$ episodes per condition, 6 tasks $\times$ 20 episodes per task) found no significant difference (Mann--Whitney $p > 0.26$, $|d| \leq 0.31$) and near-identical death rates (41.8\% vs.\ 42.5\%); reasoning depth does not meaningfully alter internal-mode outcomes.
562	
563	\section{Threshold Routing Analysis}
564	\label{sec:threshold-routing}
565	
566	Given per-task death risk knowledge, we test whether a simple threshold routing strategy can outperform always-deterministic. For each threshold $t \in [0, 1]$, we route to internal if the per-task internal death rate $\leq t$, otherwise to deterministic, and sweep all thresholds to find the optimal.
567	
568	\begin{table}[h]
569	\centering
570	\small
571	\resizebox{\columnwidth}{!}{%
572	\begin{tabular}{lccc}
573	\toprule
574	Strategy & Mean Score & Death Rate & $\Delta$ vs Det \\
575	\midrule
576	Always-det & $-9.47$ & $0.163$ & $0.00$ \\
577	Optimal threshold ($t{=}0$) & $-11.03$ & $0.155$ & $-1.56$ \\
578	Always-internal & $-39.07$ & $0.429$ & $-29.60$ \\
579	\bottomrule
580	\end{tabular}}
581	\caption{Death-risk threshold routing analysis on 245 episodes. The optimal threshold routes only \texttt{find-non-living-thing} (the sole zero-death task) to internal, with all other tasks routed to deterministic. Bootstrap 95\% CI for the difference: $[-8.87, +5.92]$.}
582	\label{tab:threshold-routing}
583	\end{table}
584	
585	Even with perfect per-task death risk knowledge, threshold routing cannot outperform always-deterministic. The sole zero-death task achieves higher scores under deterministic (+28.5) than internal (+18.9), leaving no room for a beneficial mixed strategy.
586	
587	\section{Practitioner Decision Framework}
588	\label{app:decision-framework}
589	
590	Given a new interactive environment, the following three-stage procedure diagnoses whether learned routing adds value over a fixed deterministic strategy.
591	
592	\paragraph{Stage 1: Pilot collection (${\sim}$50 episodes).}
593	Run pure-internal and pure-deterministic strategies on a representative sample (${\sim}$50 episode pairs). Compute the death-rate differential $\Delta\text{DR} = \text{DR}_{\text{int}} - \text{DR}_{\text{det}}$.
594	
595	\paragraph{Stage 2: Death dominance check.}
596	If $\Delta\text{DR} > 15$~pp, death asymmetry is likely the dominant routing signal. Compute the death-label fraction $f_{\text{death}}$: the proportion of non-tie routing labels where exactly one strategy dies.
597	
598	\paragraph{Stage 3: Decision.}
599	If $f_{\text{death}} > 75\%$, the routing signal is death-dominated; a fixed deterministic strategy will match or exceed any learned router. If $f_{\text{death}} < 50\%$, diverse routing signals may justify a learned router. Between 50\%--75\%, collect additional episodes to reduce estimation noise before committing to router development.
600	
601	\paragraph{Retrospective validation.}
602	All four experimental conditions in this paper are correctly classified:
603	
604	\begin{table}[h]
605	\centering
606	\small
607	\begin{tabular}{@{}lrrll@{}}
608	\toprule
609	Condition & $\Delta$DR & $f_{\text{death}}$ & Prediction & Actual \\
610	\midrule
611	Qwen-7B & +26.5 & 78.9\% & det-fixed & det wins \\
612	Llama-8B & +30.0 & $>$75\% & det-fixed & det wins \\
613	Qwen-72B & +27.8 & $>$75\% & det-fixed & det wins \\
614	MATH & +0.5 & 0\% & router viable & no signal \\
615	\bottomrule
616	\end{tabular}
617	\caption{Retrospective validation of the decision framework. All four conditions are correctly classified (4/4).}
618	\label{tab:decision-framework}
619	\end{table}
620	
621	The framework also predicts the inverted-U relationship between capability and death risk: below ${\sim}$0.5B parameters, agents rarely reach dangerous states (13.3\% death rate in a 15-episode pilot), so $\Delta\text{DR}$ is low and the framework would not recommend fixed-deterministic. Above ${\sim}$7B, agents are capable enough to enter catastrophic states but not capable enough to avoid them, producing high $\Delta\text{DR}$.
622	
623	\paragraph{Threshold calibration.} The thresholds above (15~pp, 75\%, 50\%) are illustrative, derived from ScienceWorld's specific reward structure (binary death penalty $P{=}100$, sparse terminal rewards). Environments with graded penalties, dense rewards, or qualitatively different failure modes may require different thresholds. Practitioners should calibrate these boundaries for their specific environment.
624	
625	\section{Extended Validation of Excluded Tasks}
626	\label{app:extended-validation}
627	
628	To verify that task exclusion does not bias toward death-prone tasks, we collect $n{=}20$ episodes for five representative excluded tasks spanning all exclusion categories (Table~\ref{tab:extended-val}).
629	
630	\begin{table}[h]
631	\centering
632	\small
633	\resizebox{\columnwidth}{!}{%
634	\begin{tabular}{lcrrrrc}
635	\toprule
636	Task & Category & $n$ & Int DR & Det DR & $\Delta$DR & D/I/N \\
637	\midrule
638	boil & dev-set & 20 & 55\% & 25\% & +30\,pp & 6/0/14 \\
639	melt & dev-set & 20 & 45\% & 20\% & +25\,pp & 7/2/11 \\
640	find-living-thing & taxonomic & 20 & 55\% & 15\% & +40\,pp & 10/0/10 \\
641	use-thermometer & agent-floor & 20 & 50\% & 20\% & +30\,pp & 7/1/12 \\
642	power-component & agent-floor & 20 & 50\% & 15\% & +35\,pp & 7/0/13 \\
643	\midrule
644	\textit{Mean (5 tasks)} & & 100 & 51.0\% & 19.0\% & +32.0\,pp & 37/3/60 \\
645	\bottomrule
646	\end{tabular}}
647	\caption{Extended validation ($n{=}20$) of representative excluded task types. All five tasks confirm death asymmetry; mean $\Delta$DR $= +32.0$\,pp is consistent with the $n{=}5$ prescreening estimate for these same tasks (Table~\ref{tab:excluded-death}).}
648	\label{tab:extended-val}
649	\end{table}
650	
651	Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\ref{tab:per-task}), indicating that excluded tasks are \emph{more} death-dominated than included tasks, the opposite of a cherry-picking bias.
652	
653	\section{Agent Prompt Templates}
654	\label{app:prompt-templates}
655	
656	Below we show the complete prompt templates used for agent interaction in ScienceWorld. Both the internal (ReAct) and deterministic strategies share the same system prompt but differ in the user message template.
657	
658	\paragraph{System prompt (shared).} Used for all ScienceWorld agent interactions across both computation modes.
659	
660	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
661	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
662	  left=2mm, right=2mm, top=1mm, bottom=1mm}
663	You are an agent interacting with a ScienceWorld text
664	environment. Your goal is to complete the given task by
665	choosing actions from the available action list.
666	
667	Use the following format for each step:
668	Thought: &lt;your reasoning about what to do next>
669	Action: &lt;exact action string from the valid actions list>
670	
671	Rules:
672	- You MUST choose an action from the valid actions list.
673	  Do not invent actions.
674	- Think step by step about what physical/scientific
675	  process is needed.
676	- Pay attention to the current observation for clues
677	  about object states.
678	\end{tcblisting}
679	
680	\paragraph{Internal (ReAct) user template.} At each step, the agent receives the current observation, valid action list, and recent action history, and must select a single action.
681	
682	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
683	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
684	  left=2mm, right=2mm, top=1mm, bottom=1mm}
685	Current observation:
686	{observation}
687	
688	Valid actions:
689	{valid_actions_str}
690	
691	Previous actions taken: {history_str}
692	
693	Choose your next action.
694	\end{tcblisting}
695	
696	\paragraph{Deterministic candidate generation template.} For the deterministic strategy, the agent generates ranked candidate actions instead of selecting one; these candidates are then evaluated via simulator forking (\S\ref{sec:method}).
697	
698	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
699	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
700	  left=2mm, right=2mm, top=1mm, bottom=1mm}
701	Current observation:
702	{observation}
703	
704	Valid actions:
705	{valid_actions_str}
706	
707	Previous actions taken: {history_str}
708	
709	Generate the top 3 most promising actions from the valid
710	actions list, ranked by how likely they are to make
711	progress on the task. Output exactly 3 actions, one per
712	line, in this format:
713	1. &lt;action>
714	2. &lt;action>
715	3. &lt;action>
716	\end{tcblisting}
717	
718	\paragraph{Reflexion self-reflection prompt.} After a failed episode, the Reflexion agent (\S\ref{sec:agent-improvement}) generates a reflection that is injected into subsequent trial attempts as additional system context.
719	
720	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
721	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
722	  left=2mm, right=2mm, top=1mm, bottom=1mm}
723	You just completed an episode in a ScienceWorld text
724	environment but failed.
725	
726	Task: {task_name}
727	Final score: {final_score}
728	Outcome: {outcome}
729	Number of steps taken: {num_steps}
730	
731	Here is a summary of your actions:
732	{action_summary}
733	
734	Analyze why this episode failed and provide a short
735	strategy for the next attempt. Focus on:
736	1. What went wrong (wrong sequence, missed key step,
737	   dangerous action)?
738	2. What should be done differently next time?
739	
740	Keep your reflection under 200 words.
741	\end{tcblisting}
742	
743	\paragraph{Grounding warning (ablation).} The prompt warning condition in the grounding ablation (Appendix~\ref{app:grounding-ablation}) appends the following to the shared system prompt:
744	
745	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
746	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
747	  left=2mm, right=2mm, top=1mm, bottom=1mm}
748	CRITICAL SAFETY RULE: The 'focus on [object]' action is
749	ONLY for submitting your final answer. Do NOT use
750	'focus on' to examine, inspect, or interact with objects
751	during exploration. Using 'focus on' on the wrong object
752	will cause irreversible failure. Use 'look at',
753	'examine', or 'pick up' instead for exploration.
754	\end{tcblisting}
755	
756	\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \emph{select} one action (ReAct), while the deterministic strategy asks it to \emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.
757	
758	\section{Non-Death Episode Case Study}
759	\label{app:non-death-case-study}
760	
761	We illustrate the framework's ability to decompose non-death routing signal using \texttt{find-non-living-thing}, the only task type with zero deaths and 100\% non-death labels (\S\ref{sec:death-decomp}). Using Gemma-2-9B-it counterfactual episodes ($N{=}20$), 12 episodes show routing preference (9 deterministic-preferred, 3 internal-preferred), confirming the framework detects bidirectional signal independent of death asymmetry.
762	
763	\paragraph{Deterministic-preferred: knowledge retrieval advantage.}
764	In Episode~3 (det: 67, int: 0), the internal strategy issues nonsensical \texttt{connect} actions for 18 consecutive steps (e.g., ``connect air to outside,'' ``connect axe to door to foundry'') without ever identifying a target object; the deterministic strategy correctly focuses on ``orange'' (+58) and opens the kitchen door (+9). In Episode~17 (det: 58, int: 50), both strategies find a valid non-living thing, but the deterministic strategy selects a higher-scoring object (orange, 58\,pts) versus the internal strategy's choice (fountain, 50\,pts), illustrating that object selection quality creates routing signal even when both strategies succeed.
765	
766	\paragraph{Internal-preferred: semantic reasoning advantage.}
767	In Episode~12 (int: 67, det: 58), the task specifies ``move it to the red box in the living room.'' The deterministic strategy focuses on the red box itself, the destination container, not a separate non-living thing, scoring 58\,pts. The internal strategy correctly distinguishes target from container, choosing ``orange'' (67\,pts). This semantic error demonstrates that deterministic pattern-matching can miss task-structure subtleties that internal reasoning captures.
768	
769	These cases confirm two properties: (1)~the framework captures non-death routing signal when it exists, and (2)~signal flows in both directions: neither strategy uniformly dominates in death-free tasks.
770	
771	\paragraph{Systematic analysis of non-death labels.}
772	All 20 non-death non-tie labels in the primary Qwen2.5-7B analysis originate from \texttt{find-non-living-thing}, the sole death-free task type. In every other task type, non-tie episodes involve at least one strategy dying. We classify the 20 episodes into three error categories:
773	
774	\begin{table}[h]
775	\centering
776	\small
777	\begin{tabular}{@{}lrrr@{}}
778	\toprule
779	Error category & Det-pref & Int-pref & Total \\
780	\midrule
781	Hallucination-induced & 8 & 2 & 10 \\
782	Object selection quality & 6 & 1 & 7 \\
783	Action selection error & 2 & 1 & 3 \\
784	\bottomrule
785	\end{tabular}
786	\caption{Non-death non-tie episode classification. Hallucination-induced: agent's state model is incorrect (e.g., believing \texttt{eat} completes the task). Object selection quality: both strategies succeed but choose different-value objects. Action selection: correct state model but suboptimal action sequences.}
787	\label{tab:non-death-taxonomy}
788	\end{table}
789	
790	\noindent Hallucination-induced errors dominate (50\%), driven by a recurring ``eat before focus'' pattern: the internal strategy consumes the target object (destroying it) before attempting the scoring action (\texttt{focus on}), indicating an incorrect state model that equates eating with task completion (11 of 20 episodes). Object selection quality accounts for 35\%: typically the deterministic strategy selecting ``orange'' (58\,pts) while the internal strategy settles for lower-value objects (``fountain'' or ``picture,'' 50\,pts). The error categories are bidirectional: 2 of 10 hallucination episodes and 1 of 3 action selection episodes are internal-preferred, confirming the framework detects failures in both strategies. Score gaps reflect category severity: hallucination errors produce large gaps ($17$--$67$\,pts, one strategy scores zero) while object selection differences produce small gaps ($8$--$9$\,pts, both strategies functional).
791	
792	\section{Use of AI Assistants}
793	\label{app:ai-assistants}
794	
795	We used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:
796	\begin{itemize}
797	    \item \textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.
798	    \item \textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting \LaTeX{}.
799	    \item \textbf{Literature:} summarizing related papers to inform the related-work section.
800	\end{itemize}
801	
802	\end{document}
803	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "188795a4-3eda-4a9a-acd5-4b9319c5bd1d",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "0f9807a2-6fa2-4d8f-8ce8-02e7b209f851",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\n\\usepackage[review]{acl}\n\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{graphicx}\n\\graphicspath{{figures/}}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{algorithm}\n\\usepackage{algorithmic}\n\\usepackage{caption}\n\\usepackage{tcolorbox}\n\\tcbuselibrary{listings,breakable}\n\n\\renewcommand{\\topfraction}{0.9}\n\\renewcommand{\\dbltopfraction}{0.9}\n\\renewcommand{\\bottomfraction}{0.8}\n\\renewcommand{\\textfraction}{0.1}\n\n\\hypersetup{pdfauthor={},pdftitle={}}\n\n\\title{Death Avoidance as the Dominant Routing Signal:\\\\A Counterfactual Analysis on ScienceWorld}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\\input{introduction}\n\\input{related_work}\n\\input{method}\n\\input{experiments}\n\\input{discussion}\n\\input{conclusion}\n\n\\section*{Limitations}\nFull quantitative validation (DAF, label fractions) is specific to ScienceWorld; MATH and ALFWorld serve as boundary probes, not comprehensive cross-environment validation. DAF depends on a fixed death penalty ($P{=}100$); environments with graded or stochastic failure severity would require extensions (Appendix~\\ref{app:penalty}). The internal baseline uses single-pass ReAct~\\citep{react-2023}; more aggressive self-correction (e.g., Tree-of-Thought) may further reduce death rates and alter the signal composition. With $K{=}11$ task-type clusters, cluster bootstrap yields wider CIs; wild cluster bootstrap ($p < 0.001$; Appendix~\\ref{app:wild-cluster}) and 100\\% directional consistency across all 28 death-prone tasks provide partial mitigation.\n\n\\bibliography{references}\n\n\\appendix\n\n\\noindent\\textbf{Appendix Overview.}\n\\hyperref[app:sci]{A.~Signal Concentration Index} $\\cdot$\n\\hyperref[app:labeling]{B.~Labeling Quality Audit} $\\cdot$\n\\hyperref[app:per-task]{C.~Per-Task Decomposition} $\\cdot$\n\\hyperref[app:correlation]{D.~Correlation Robustness} $\\cdot$\n\\hyperref[app:wild-cluster]{E.~Cluster Bootstrap Sensitivity} $\\cdot$\n\\hyperref[app:per-task-ci]{F.~Per-Task CIs} $\\cdot$\n\\hyperref[app:loto-daf]{G.~Leave-One-Task-Out DAF} $\\cdot$\n\\hyperref[app:dose-response]{H.~Dose-Response Breakdown} $\\cdot$\n\\hyperref[app:router-details]{I.~Router Training Details} $\\cdot$\n\\hyperref[app:seed-robustness]{J.~Seed Robustness} $\\cdot$\n\\hyperref[app:penalty]{K.~Penalty Sensitivity} $\\cdot$\n\\hyperref[app:cross-env-details]{L.~Cross-Environment Details} $\\cdot$\n\\hyperref[app:cross-model]{M.~Cross-Model Verification} $\\cdot$\n\\hyperref[app:failure-modes]{N.~Failure Mode Analysis} $\\cdot$\n\\hyperref[app:grounding-ablation]{O.~Grounding Ablation} $\\cdot$\n\\hyperref[app:ablations]{P.~Ablation Studies} $\\cdot$\n\\hyperref[sec:threshold-routing]{Q.~Threshold Routing} $\\cdot$\n\\hyperref[app:decision-framework]{R.~Decision Framework} $\\cdot$\n\\hyperref[app:extended-validation]{S.~Extended Validation} $\\cdot$\n\\hyperref[app:prompt-templates]{T.~Agent Prompt Templates} $\\cdot$\n\\hyperref[app:non-death-case-study]{U.~Non-Death Episode Case Study}\n\n\\section{Signal Concentration Index}\n\\label{app:sci}\n\nLet $K$ denote the number of task types and $c_k$ the contribution of task type $k$ to the aggregate routing signal, defined as the fraction of total death-rate differential attributable to task $k$:\n\\begin{equation}\n    c_k = \\frac{n_k \\cdot \\delta_k}{\\sum_{j=1}^{K} n_j \\cdot \\delta_j}\n\\end{equation}\nwhere $n_k$ is the number of episodes and $\\delta_k = d_k^{\\tt int} - d_k^{\\tt det}$ is the per-task death-rate differential. The SCI is the Gini coefficient over $\\{c_1, \\ldots, c_K\\}$:\n\\begin{equation}\n    \\text{SCI} = \\frac{\\sum_{i=1}^K \\sum_{j=1}^K |c_i - c_j|}{2K \\sum_{k=1}^K c_k}\n\\end{equation}\n\n\\section{Labeling Quality Audit}\n\\label{app:labeling}\n\nNote that episode-level labels are used to evaluate step-level predictions, introducing a granularity mismatch rather than independent validation. A potential concern is oracle circularity: whether episode-level labels reflect tie-breaking artifacts rather than genuine computation mode differences. We audit all 245 labels. Of the 150 \\texttt{no\\_preference} labels (61.2\\%), 115 (46.9\\%) are both-alive ties and 35 (14.3\\%) are both-dead, all excluded from router training. The remaining 95 training labels are entirely genuine: 75 from death asymmetry (70 deterministic-preferred, 5 internal-preferred) and 20 from score comparison with both strategies surviving (16 deterministic-preferred, 4 internal-preferred). Zero labels depend on tie-breaking. Retraining the router using only death-asymmetry labels yields step-level balanced accuracy of 57.3\\%, within 1$\\sigma$ of the full-label retrain (57.6 $\\pm$ 0.5\\%, step-level Trainer evaluation); score-comparison labels contribute negligible additional signal. (Step-level metrics are used here for the relative comparison; as shown in \\S\\ref{sec:router-diagnostic}, absolute generalization to new episodes is near chance.) The 97.4\\% step-level tie rate (\\S\\ref{sec:collection}) further motivates episode-level over step-level labeling.\n\n\\section{Per-Task Decomposition}\n\\label{app:per-task}\nWe use ScienceWorld v1.2.3~\\citep{scienceworld-2022}.\nWe select 11 of ScienceWorld's 30 task types for analysis. Types are excluded when they were used for pipeline development (5 tasks, standard hold-out practice), are taxonomically redundant with a retained family representative (7 tasks), or exhibit near-zero task progress under both strategies (7 tasks, agent capability floor).\\footnote{Excluded tasks exhibit even stronger death dominance than included tasks ($\\Delta\\text{DR} = +38.2$\\,pp vs.\\ $+28.7$\\,pp; Table~\\ref{tab:excluded-death}).}\n\n\\paragraph{Task selection and anti-cherry-picking.}\nEighteen of the 19 excluded task types (95\\%) exhibit death-asymmetric patterns (Table~\\ref{tab:excluded-death}): internal-reasoning death rates range from 40\\% to 60\\% (mean 53.9\\%), while deterministic death rates range from 0\\% to 40\\% (mean 15.8\\%), yielding a mean death-rate differential of $+38.2$\\,pp, exceeding the $+28.7$\\,pp for included tasks. The included subset is thus \\emph{less} death-asymmetric than the excluded subset, the opposite of what a cherry-picking hypothesis would predict. The sole exception is \\texttt{grow-plant}, an intrinsically safe task with zero deaths under both strategies, paralleling \\texttt{find-non-living-thing} in the included set. The 19 excluded tasks fall into three independently motivated categories: five used during pipeline development (standard hold-out practice), seven taxonomically redundant with included family representatives (deduplication), and seven where the 7B backbone achieves near-zero task progress regardless of strategy (agent capability floor). In no case was a task excluded because death dominance was absent. Exclusion is driven by absence of non-death routing signal ($\\Delta_{\\text{nd}} = 0$ for 53\\% of excluded tasks) and standard deduplication practices. \\texttt{find-non-living-thing} serves as an internal counterexample: zero deaths under both strategies yet included because it exhibits non-death routing signal ($\\Delta_{\\text{full}} = +9.58$ entirely from score differences), and deterministic is not always preferred (4 of 20 non-tie labels favor internal).\n\n\\begin{table}[t]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrcccl@{}}\n\\toprule\nTask & Grp & $n$ & D\\%\\textsubscript{int} & D\\%\\textsubscript{det} & $\\Delta$DR & Excl.\\ reason \\\\\n\\midrule\nboil                          & A & 20 & 50 & 20 & $+30$ & dev set \\\\\nchange-state-of-matter        & A & 20 & 55 & 15 & $+40$ & dev set \\\\\nchem-mix-paint-secondary      & A & 20 & 45 & 10 & $+35$ & dev set \\\\\ngrow-plant                    & A & 20 &  0 &  0 & $\\phantom{+}0$  & dev set \\\\\nmelt                          & A & 20 & 55 & 15 & $+40$ & dev set \\\\\n\\midrule\nchem-mix-paint-tertiary       & B &  5 & 40 & 20 & $+20$ & family redundancy \\\\\nfind-living-thing             & B &  5 & 60 & 20 & $+40$ & family redundancy \\\\\nfind-plant                    & B &  5 & 60 &  0 & $+60$ & family redundancy \\\\\ninclined-friction-named       & B &  5 & 60 & 20 & $+40$ & family redundancy \\\\\ninclined-friction-unnamed     & B &  5 & 60 &  0 & $+60$ & family redundancy \\\\\nlifespan-shortest             & B &  5 & 60 & 40 & $+20$ & family redundancy \\\\\nmeasure-melt-known            & B &  5 & 60 &  0 & $+60$ & family redundancy \\\\\n\\midrule\nmendelian-known               & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\nmendelian-unknown             & C &  5 & 60 & 40 & $+20$ & agent floor \\\\\npower-component               & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\npower-renewable               & C &  5 & 60 &  0 & $+60$ & agent floor \\\\\ntest-conductivity             & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\ntest-conductivity-unknown     & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\nuse-thermometer               & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\n\\midrule\n\\textbf{Mean (19 excluded)}   &   &    & \\textbf{53.9} & \\textbf{15.8} & $\\mathbf{+38.2}$ & \\\\\n\\textit{cf.\\ included (11)}   &   &    & \\textit{46.5} & \\textit{17.8} & $\\textit{+28.7}$ & \\\\\n\\bottomrule\n\\end{tabular}}%\n\\caption{Death-rate analysis of all 19 excluded task types. D\\%: death rate (score $\\leq -100$). $\\Delta$DR = D\\%\\textsubscript{int} $-$ D\\%\\textsubscript{det}. 18 of 19 excluded tasks (95\\%) exhibit positive death asymmetry ($\\Delta$DR $\\geq +20$\\,pp). Exclusion groups: A = development set (excluded to prevent circular evaluation), B = taxonomically redundant with an included family representative, C = agent-floor tasks (backbone achieves near-zero progress regardless of strategy). The mean $\\Delta$DR among excluded tasks ($+38.2$\\,pp) exceeds that of included tasks ($+28.7$\\,pp), confirming that task selection does not bias toward death-prone tasks. Group B--C estimates are based on $n{=}5$ prescreening episodes per task and should be interpreted as directional evidence rather than precise rate estimates.}\n\\label{tab:excluded-death}\n\\end{table}\n\n\\section{Correlation Robustness}\n\\label{app:correlation}\n\nThe Pearson $r = 0.9698$ reported in \\S\\ref{sec:death-decomp} is robust across multiple diagnostics. Spearman rank correlation is $\\rho = 0.986$ ($p = 2.4 \\times 10^{-8}$); the relationship is not driven by outliers or non-linearity. A nonparametric bootstrap (10{,}000 resamples) yields 95\\% CI $[0.952, 0.995]$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lr@{}}\n\\toprule\nTask removed & $r_{\\text{LOO}}$ \\\\\n\\midrule\nid-life-stages-1       & 0.963 \\\\\nlifespan-long          & 0.969 \\\\\nlifespan-l-then-s      & 0.976 \\\\\ninclined-plane         & 0.969 \\\\\nfreeze                 & 0.971 \\\\\nmeas-melt-point        & 0.972 \\\\\nid-life-stages-2       & 0.972 \\\\\nfind-animal            & 0.970 \\\\\ngrow-fruit             & 0.973 \\\\\nchem-mix               & 0.969 \\\\\nfind-non-living-thing  & 0.980 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\\ $\\Delta_{\\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}\n\\label{tab:loo}\n\\end{table}\n\n\\section{Cluster Bootstrap Sensitivity Analysis}\n\\label{app:wild-cluster}\n\nWith $K{=}11$ task-type clusters, cluster bootstrap falls well below the $K{\\geq}20$--50 recommended for reliable inference \\citep{cameron-2008,webb-2023}. The narrower CIs obtained reflect known small-sample bias toward underestimation of variance, not tighter inference.\n\nEpisodes within the same task type share environment dynamics, raising the concern that the effective sample size is closer to $K$ (task types) than $N$ (episodes). We address this with cluster-robust inference treating each task type as a cluster ($K{=}11$, all 11 included task types, 245 episodes).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nMethod & $p$-value & 95\\% CI \\\\\n\\midrule\nCluster-robust $t$-test ($t{=}10.0$, df$=$10) & $< 0.001$ & $[0.73, 1.00]$ \\\\\nWild cluster bootstrap ($B{=}9{,}999$) & $< 0.001$ & $[0.73, 1.00]$ \\\\\nExact permutation ($2{,}048$ perms) & $0.002$ & --- \\\\\nSign test & $< 0.001$ & --- \\\\\n\\bottomrule\n\\end{tabular}}%\n\\caption{Cluster-level tests of death-rate asymmetry ($K{=}11$ task clusters, 245 episodes). 10 of 11 clusters show internal DR $>$ deterministic DR; the sole exception (\\texttt{find-non-living-thing}) has zero deaths under both strategies. Cohen's $d = 3.02$. The exact permutation $p = 0.002$ ($4/2{,}048$) reflects the near-unanimous directional consistency.}\n\\label{tab:wild-cluster}\n\\end{table}\n\n\\noindent All methods confirm significance with $p < 0.01$, and the 95\\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.\n\nWe retain this analysis for transparency; readers should rely on the non-clustered episode-level bootstrap (\\S\\ref{sec:death-decomp}) as the primary inference.\n\n\\section{Per-Task Death Rate Confidence Intervals}\n\\label{app:per-task-ci}\n\nWe compute bootstrap 95\\% CIs for the death-rate differential ($\\Delta\\text{DR} = \\text{DR}_{\\text{int}} - \\text{DR}_{\\text{det}}$) for all 30 ScienceWorld task types. Of 30 tasks, 28 are death-prone (at least one death under either strategy); the remaining 2 (\\texttt{grow-plant}, \\texttt{find-non-living-thing}) have zero deaths under both strategies.\n\nAcross all 28 death-prone tasks, internal DR exceeds deterministic DR without exception (100\\% directional consistency). The pooled death-rate differential is $+37.3\\%$ (95\\% CI: $[29.7\\%, 44.4\\%]$). Fifteen of 28 tasks are individually significant (CI excludes zero); the 13 non-significant tasks all have $n{=}5$ prescreening episodes, where statistical power is insufficient to detect even large effects (e.g., a task with $\\Delta\\text{DR} = +40$\\,pp at $n{=}5$ has a CI of $\\pm 43$\\,pp). The universal directional consistency, combined with the pooled significance, confirms that death asymmetry is not driven by a subset of outlier tasks.\n\n\\section{Leave-One-Task-Out DAF Sensitivity}\n\\label{app:loto-daf}\n\nTable~\\ref{tab:loto-daf} (main text, \\S\\ref{sec:death-decomp}) reports the full leave-one-task-out DAF sensitivity analysis.\n\n\\section{Per-Task Dose-Response Breakdown}\n\\label{app:dose-response}\n\nTable~\\ref{tab:dose-response-detail} reports per-task death rates for Reflexion at $N{=}3$, 4, and 5 on the 10 death-prone tasks ($n{=}20$ episodes per task). Per-task variance is high (up to 25\\,pp range for \\texttt{measure-melting-point}), but the aggregate smooths to a 2.5\\,pp band, confirming that the stabilization conclusion is robust at the aggregate level despite task-level noise. \\texttt{freeze} is consistently the hardest task (50--60\\% DR across all $N$).\n\n\\paragraph{Statistical power.} With $n{=}200$ paired episodes, the minimum detectable effect (MDE) is ${\\sim}8$~pp ($\\alpha = 0.05$, 80\\% power). The key $N{=}1{\\to}3$ decline ($-13.5$~pp) exceeds this threshold and is well-powered; the stabilization claim ($N{=}3{\\to}5$, $+1.0$~pp) is also supported, since a ${\\geq}8$~pp improvement would be detected if present.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-task death rates (\\%) for Reflexion at $N{=}3$, 4, 5 on 10 death-prone tasks ($n{=}20$ per task). Aggregate death rates confirm stabilization at $N \\geq 3$ (range: $34.0$--$36.5\\%$).}\n\\label{tab:dose-response-detail}\n\\begin{tabular}{@{}lrrr@{}}\n\\toprule\nTask & $N{=}3$ & $N{=}4$ & $N{=}5$ \\\\\n\\midrule\nchemistry-mix & 25.0 & 35.0 & 20.0 \\\\\nfind-animal & 45.0 & 30.0 & 45.0 \\\\\nfreeze & 50.0 & 50.0 & 60.0 \\\\\ngrow-fruit & 30.0 & 25.0 & 25.0 \\\\\nidentify-life-stages-1 & 35.0 & 35.0 & 35.0 \\\\\nidentify-life-stages-2 & 25.0 & 25.0 & 30.0 \\\\\ninclined-plane-angle & 20.0 & 30.0 & 35.0 \\\\\nlifespan-longest & 45.0 & 40.0 & 40.0 \\\\\nlifespan-long+short & 30.0 & 45.0 & 35.0 \\\\\nmeasure-melting-pt & 35.0 & 50.0 & 25.0 \\\\\n\\midrule\n\\textbf{Aggregate} & \\textbf{34.0} & \\textbf{36.5} & \\textbf{35.0} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Router Training Details}\n\\label{app:router-details}\n\nWe use Qwen3-1.7B for the router to avoid circular dependency with the Qwen2.5-7B data-generating model.\n\nWith gradient accumulation of 1 (effective batch size 4), routing performance is highly sensitive to the evaluation split; this suggests overfitting to specific train/validation partition boundaries. With gradient accumulation of 8 (effective batch size 32), step-level performance stabilizes across splits (${\\sim}54\\%$ balanced accuracy). All reported results use gradient accumulation 8.\n\nUnder step-level evaluation with a fixed data split, cross-seed balanced accuracy ranges from 52.7\\% to 58.1\\%, but internal recall varies from 51.5\\% to 81.8\\%, which reflects threshold sensitivity. However, episode-level evaluation reveals that this apparent discrimination does not generalize: balanced accuracy drops to $47.1 \\pm 2.2\\%$ across 8 cross-split seeds (Appendix~\\ref{app:seed-robustness}). Deployed end-to-end, the trained router allocates 97.0\\% of episodes to deterministic computation with 17.6\\% death rate, and misrouting cost (death from internally-routed episodes) exceeds the benefit of correctly routing rare internal-preferred cases.\n\n\\paragraph{Evaluation methods.} All results use \\emph{generation-based evaluation}: the model generates a routing label as text (\\texttt{enable\\_thinking=False}), parsed for classification. We evaluate at two granularities: \\emph{step-level} (steps from the same episode may appear in both train and validation sets) and \\emph{episode-level} (entire episodes held out). Step-level accuracy ($54.1 \\pm 5.4\\%$) exceeds chance (the router captures some signal), but episode-level accuracy ($47.1 \\pm 2.2\\%$, below chance) shows this does not generalize to unseen episodes. Paraphrase-based text augmentation (Appendix~\\ref{app:seed-robustness}) provides no improvement; real-data scaling remains open. Always-deterministic is trivially near-optimal given DAF $= 90.4\\%$. The main text (\\S\\ref{sec:router-diagnostic}) reports controlled 4-seed results at three scales; the model-size ablation (Appendix~\\ref{app:ablations}) provides further detail.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nHyperparameter & Classification Head & Implicit Router \\\\\n\\midrule\nBase model & Qwen3-1.7B & Qwen3-1.7B \\\\\nArchitecture & Linear + LoRA & SFT + LoRA \\\\\nLoRA $r$ / $\\alpha$ & 16 / 32 & 16 / 32 \\\\\nLearning rate & 2e-5 & 2e-4 \\\\\nOptimizer & AdamW & AdamW \\\\\nEpochs & 3 & 3 \\\\\nBatch size (per device) & 4 & 4 \\\\\nGradient accumulation & 8 & 8 \\\\\nWarmup ratio & 0.1 & 0.1 \\\\\nWeight decay & 0.01 & 0.01 \\\\\nMax sequence length & 512 & 512 \\\\\nSeeds & \\{42\\} & \\{42, 123, 456, 789\\} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Router training hyperparameters. Both architectures use the same base model with LoRA adaptation. The classification head degenerates across all configurations; the implicit router results are reported as 4-seed mean$\\pm$std.}\n\\label{tab:hyperparams}\n\\end{table}\n\n\\paragraph{Agent inference parameters.}\nFor ScienceWorld, each agent step uses temperature $T{=}0.3$ and maximum generation length of 256 tokens, served via vLLM v0.21.0. Top-$p$ is left at the vLLM default of $1.0$ (no nucleus sampling). For MATH, the agent uses greedy decoding ($T{=}0.0$) with a maximum of 2{,}048 tokens per generation. For ALFWorld, we use $T{=}0.3$ with 256 maximum tokens. All three environments use Qwen2.5-7B-Instruct~\\citep{qwen25-2024} as the backbone.\n\n\\section{Seed Robustness}\n\\label{app:seed-robustness}\n\n\\paragraph{Counterfactual collection seed.}\nWe re-collect all episodes with a different ScienceWorld environment seed (seed=123, $N{=}220$, 20 episodes per task type).\nThe replication yields DAF $= 89.7\\%$ ($\\Delta_\\text{nd} = 2.83$, $\\Delta_\\text{full} = 27.47$),\nwithin 0.73~pp of the primary estimate (seed=42, DAF $= 90.4\\%$).\nLabel distributions are consistent: 67 deterministic-preferred / 7 internal-preferred / 146 no-preference\n(primary: 86 / 9 / 150).\nDeath rates by strategy remain directionally aligned ($\\text{DR}_\\text{int} = 45.5\\%$ vs.\\ $42.9\\%$; $\\text{DR}_\\text{det} = 20.9\\%$ vs.\\ $16.3\\%$).\nThe seed=123 replication uses $N{=}220$ ($20$ episodes per task type);\nthe primary dataset's larger $N{=}245$ reflects 25 additional episodes across two task types (\\texttt{find-non-living-thing}: $n{=}40$; \\texttt{lifespan-longest-lived}: $n{=}25$; all others: $n{=}20$).\n\n\\paragraph{Router training seed.}\nWe assess router generalization at two evaluation granularities: \\emph{step-level}, where steps from the same episode may appear in both train and validation sets, and \\emph{episode-level}, where entire episodes are held out. Both use cross-split evaluation (seeds $\\{42, \\ldots, 49\\}$, 8 seeds total), where the data partition and training seed both vary. Table~\\ref{tab:seed-robustness} reports per-seed results.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}llcc@{}}\n\\toprule\nEval.\\ Granularity & Seed & Bal.\\ Acc.\\ (\\%) \\\\\n\\midrule\nStep-level & 42 & 57.06 \\\\\n(same-episode & 43 & 63.99 \\\\\nleakage) & 44 & 55.43 \\\\\n & 45 & 56.14 \\\\\n & 46 & 55.45 \\\\\n & 47 & 50.08 \\\\\n & 48 & 48.03 \\\\\n & 49 & 59.30 \\\\\n\\cmidrule{2-3}\n & Mean$\\pm$std & $54.1 \\pm 5.4$ \\\\\n\\midrule\nEpisode-level & 42 & 48.1 \\\\\n(held-out & 43 & 47.9 \\\\\nepisodes) & 44 & 49.6 \\\\\n & 45 & 49.4 \\\\\n & 46 & 48.5 \\\\\n & 47 & 43.1 \\\\\n & 48 & 45.4 \\\\\n & 49 & 44.8 \\\\\n\\cmidrule{2-3}\n & Mean$\\pm$std & $47.1 \\pm 2.2$ \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{Always-det (= majority-vote)} & 50.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-seed router performance under cross-split evaluation (8 seeds, generation-based, \\texttt{enable\\_thinking=False}). Step-level evaluation allows steps from the same episode in both train and validation sets (same-episode leakage). Episode-level evaluation holds out entire episodes; the resulting $47.1 \\pm 2.2\\%$ is below the 50\\% chance baseline. A text augmentation ablation (Table~\\ref{tab:text-augmentation}) confirms this failure persists under the current data distribution and augmentation regime.}\n\\label{tab:seed-robustness}\n\\end{table}\n\nThe contrast between step-level ($54.1 \\pm 5.4\\%$) and episode-level ($47.1 \\pm 2.2\\%$) evaluation reveals a generalization gap: the step-level signal likely reflects memorization of episode-specific context (enabled by same-episode leakage) rather than extraction of generalizable routing features. At episode level, the router performs below chance across all 8 seeds (range: 43.1\\%--49.6\\%). Paraphrase-based text augmentation (Table~\\ref{tab:text-augmentation}) from 25\\% to 800\\% ($32{\\times}$ range) provides no improvement, converging to the always-deterministic baseline ($50\\%$). Paraphrase augmentation inflates the majority class without generating novel routing patterns; genuine episode-level scaling (collecting more counterfactual pairs) remains an open question. With DAF $= 90.4\\%$ and all task types deterministic-majority (86:9 label ratio), always-deterministic trivially solves the episode-level routing problem, leaving the step-level router with no exploitable signal under current architectures.\n\n\\paragraph{Text augmentation ablation.} To test whether the episode-level generalization failure stems from data scarcity, we vary training set size from 25\\% to 800\\% of the original via paraphrase-based text augmentation (synonym substitution + template variation on step observations), holding the episode-level validation set fixed. This tests augmentation-based scaling, not genuine episode-level scaling (which would require new counterfactual collections). Table~\\ref{tab:text-augmentation} reports the results.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}rccc@{}}\n\\toprule\nScale & Samples & Det\\% & Ep.\\ Bal.\\ Acc.\\ (\\%) \\\\\n\\midrule\n25\\% & 433 & ${\\sim}90$ & $49.5 \\pm 0.3$ \\\\\n50\\% & 867 & ${\\sim}90$ & $51.5$ \\\\\n100\\% & 1{,}735 & 89.6 & $49.9 \\pm 0.1$ \\\\\n200\\% & 3{,}470 & 94.2 & $50.0 \\pm 0.0$ \\\\\n800\\% & 13{,}880 & ${\\sim}97.7$ & $51.0 \\pm 1.1$ \\\\\n\\midrule\nAlways-det & --- & --- & 50.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Text augmentation ablation: episode-level balanced accuracy across training set sizes (25\\%--800\\% of original via paraphrase, $32{\\times}$ range). Internal recall $= 0.0$ at all scales (complete majority-class collapse). Det\\%: fraction of deterministic-preferred labels in training data. The 50\\% scale is a single seed; all others report mean$\\pm$std across seeds.}\n\\label{tab:text-augmentation}\n\\end{table}\n\nAll scales hover at ${\\sim}50\\%$ episode-level balanced accuracy (equivalent to the always-deterministic baseline), with no monotonic improvement as data increases. Augmentation-based scaling provides no improvement at any scale; however, episode-level minority-class diversity remains a potential confound that cannot be resolved without collecting more internal-preferred episodes. The ground-truth internal-preferred rate (9/245 $= 3.7\\%$) means collecting 50 internal-preferred episodes would require approximately 1{,}350 paired episodes at current environment dynamics, a $5.5{\\times}$ expansion with diminishing return on a $9.6\\%$ signal. The failure points to a limitation of the current data distribution: when DAF $= 90.4\\%$ and all task types are deterministic-majority (86:9 label ratio), the episode-level routing problem is trivially solved by always choosing deterministic, and the step-level router finds no exploitable signal under the current architecture and data regime.\n\nAugmentation disproportionately increases the majority (deterministic) class: Det\\% rises from 89.6\\% at 100\\% to 94.2\\% at 200\\% and ${\\sim}97.7\\%$ at 800\\%. However, the complete collapse to majority-class prediction (internal recall $= 0.0$) occurs even at the smallest unaugmented scale (25\\%, ${\\sim}90\\%$ det); this is not an augmentation artifact. Balanced accuracy corrects for class imbalance by averaging per-class recall, so the metric itself is not biased by the skew.\n\nDecomposition metrics are stable under bootstrap resampling ($B{=}10{,}000$ resamples of the 245-episode dataset): DAF $= 90.4\\% \\pm 4.2\\%$ (95\\% CI $[81.3\\%, 99.1\\%]$); Pearson $r = 0.975 \\pm 0.011$ (95\\% CI $[0.952, 0.995]$). The death avoidance dominance finding is robust to both resampling and split perturbation.\n\n\\paragraph{Per-task-type evaluation breakdown.} To test whether the router learns transferable routing strategies or merely task-type classification, we evaluate existing checkpoints (8 seeds) separately on each of the 11 task types. Of the 11 task types, 7 have \\emph{all-deterministic} labels (no internal-preferred episodes exist), making balanced accuracy undefined; the router has nothing to learn beyond the trivial always-deterministic default. For the remaining 4 task types where both classes are present, balanced accuracy ranges from 50.0\\% to 73.0\\%, but this apparent signal does not indicate cross-task-type routing transfer: the router is effectively classifying task types (which correlate with death risk) rather than extracting a generalizable routing strategy. This complements the text augmentation ablation: routing signal does not transfer across task types because the signal \\emph{is} the task type, i.e., whether a given task carries death risk. The 4B capacity scaling result (Appendix~\\ref{app:ablations}) suggests capacity is one factor, but even 4B's $59.0\\%$ episode-level accuracy does not demonstrate cross-task-type transfer.\n\n\\section{Penalty Sensitivity Analysis}\n\\label{app:penalty}\n\nTable~\\ref{tab:penalty-sensitivity} (main text, \\S\\ref{sec:daf}) reports DAF sensitivity across penalty magnitudes.\n\nThe non-death score gap $\\Delta_{\\text{nd}} = 2.84$ is invariant across penalty levels; it depends only on surviving-episode performance, not on $P$. As $P$ increases, $\\Delta_{\\text{full}}$ grows ($16.33$ at $P{=}50$, $29.60$ at $P{=}100$, $56.13$ at $P{=}200$) while $\\Delta_{\\text{nd}}$ remains fixed, mechanically increasing DAF.\n\n\\paragraph{Mechanism boundary: death specificity.}\nThe $r = 0.97$ correlation between per-task death-rate differential and $\\Delta_{\\text{full}}$ is specific to catastrophic death (score $= -100$). Broader failure definitions dissolve the correlation entirely: defining ``failure'' as any non-positive score ($T{=}0$) yields $r = -0.13$ ($p = 0.70$), because non-death episodes show near-zero performance differential between strategies ($\\Delta_{\\text{nd}} = 2.84$). Table~\\ref{tab:penalty-correlation} quantifies this specificity across penalty magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}rccl@{}}\n\\toprule\n$P$ & $r$ & $p$ & Sig.\\ ($\\alpha{=}0.05$) \\\\\n\\midrule\n1 & $-0.44$ & $0.178$ & No \\\\\n5 & $-0.29$ & $0.382$ & No \\\\\n10 & $-0.08$ & $0.813$ & No \\\\\n25 & $0.51$ & $0.108$ & No \\\\\n50 & $0.86$ & $0.0006$ & Yes \\\\\n100\\textsuperscript{*} & $0.97$ & $8 \\times 10^{-7}$ & Yes \\\\\n200 & $0.99$ & $1 \\times 10^{-9}$ & Yes \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Pearson $r$ between per-task death-rate differential and $\\Delta_{\\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \\geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \\textsuperscript{*}Default ScienceWorld setting.}\n\\label{tab:penalty-correlation}\n\\end{table}\n\nThis sharpens our central finding: death is not merely the dominant component of routing signal; it is effectively the \\emph{only} component that generates differential routing signal in ScienceWorld. At low penalties, the death contribution is small and $\\Delta_{\\text{full}}$ reduces to $\\Delta_{\\text{nd}} \\approx 2.84$, which is near-uniform across task types ($\\text{mean non-death gap} = -1.19$ excluding the \\texttt{find-non-living-thing} outlier); consequently, death-rate differential has no predictive power. As $P$ increases, the death term dominates $\\Delta_{\\text{full}}$, and the correlation sharpens because death rates \\emph{are} the performance gap. The DAF values in Table~\\ref{tab:penalty-sensitivity} increase monotonically with $P$, but this is a mathematical consequence of the decomposition ($\\text{DAF} = \\delta P / (\\delta P + \\Delta_{\\text{nd}})$), not evidence of mechanism robustness.\n\n\\section{Cross-Environment Details}\n\\label{app:cross-env-details}\n\nTable~\\ref{tab:cross-env} summarizes the label distributions across all three environments (see also Figure~\\ref{fig:signal-reversal} in \\S\\ref{sec:cross-env}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nEnvironment & $N$ & Det\\% & Int\\% & NoPref\\% & Death? \\\\\n\\midrule\nScienceWorld & 245 & 35.1 & 3.7 & 61.2 & Yes ($-100$) \\\\\nMATH & 795 & 7.3 & 8.3 & 84.4 & No \\\\\nALFWorld & 135 & 25.9 & 1.5 & 72.6 & No\\textsuperscript{$\\dagger$} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-environment label distribution. ``Deterministic'' denotes qualitatively different computation modes: ScienceWorld = oracle simulator with ground-truth state; MATH = Python code interpreter; ALFWorld = admissible-action enumeration. $\\dagger$\\,ALFWorld's deterministic advantage stems from information asymmetry, not death avoidance.}\n\\label{tab:cross-env}\n\\end{table}\n\nTable~\\ref{tab:alfworld-pertask} provides the per-task-type breakdown for ALFWorld. Unlike ScienceWorld, ALFWorld has no death mechanism ($\\delta = 0$, DAF $= 0\\%$); the entire performance gap $\\Delta_{\\text{full}}$ reflects information asymmetry from admissible-action access. \\texttt{pick\\_and\\_place} shows the strongest effect ($\\Delta = 0.563$, 18 of 32 episodes det-preferred), while \\texttt{pick\\_two\\_obj\\_and\\_place} shows the weakest ($\\Delta = 0.087$), consistent with multi-object tasks requiring more sequential reasoning that admissible actions alone cannot resolve. Only \\texttt{pick\\_heat\\_then\\_place} has a 95\\% CI crossing zero ($n{=}16$).\n\n\\begin{table}[h]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2.5pt}\n\\begin{tabular}{@{}lrcccc@{}}\n\\toprule\nTask Type & $n$ & Succ\\%\\textsubscript{int} & Succ\\%\\textsubscript{det} & D / I / N & $\\Delta_{\\text{full}}$ \\\\\n\\midrule\npick\\_and\\_place       & 32 & 0.0  & 56.3 & 18 / 0 / 14 & $+0.563$ \\\\\nlook\\_at\\_obj\\_in\\_light & 13 & 15.4 & 38.5 & 3 / 0 / 10  & $+0.231$ \\\\\npick\\_cool\\_then\\_place & 24 & 0.0  & 16.7 & 4 / 0 / 20  & $+0.167$ \\\\\npick\\_clean\\_then\\_place & 27 & 3.7  & 18.5 & 5 / 1 / 21  & $+0.148$ \\\\\npick\\_heat\\_then\\_place & 16 & 6.3  & 18.8 & 3 / 1 / 12  & $+0.125$ \\\\\npick\\_two\\_obj\\_and\\_place & 23 & 0.0 & 8.7  & 2 / 0 / 21  & $+0.087$ \\\\\n\\midrule\n\\textbf{All (6 types)} & \\textbf{135} & \\textbf{3.0} & \\textbf{27.4} & \\textbf{35 / 2 / 98} & $\\mathbf{+0.244}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\\Delta_{\\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\\Delta_{\\text{full}}$ descending.}\n\\label{tab:alfworld-pertask}\n\\end{table}\n\n\\paragraph{MATH subset composition.}\nThe $N{=}795$ MATH problems span two categories from the MATH test set~\\citep{math-2021} (Levels 4--5): Algebra (585, 73.6\\%) and Counting \\& Probability (210, 26.4\\%). The category imbalance reflects the relative sizes in the original test set.\n\n\\section{Cross-Model Verification}\n\\label{app:cross-model}\n\nWe replicate the counterfactual analysis with Llama-3.1-8B-Instruct across all 11 task types ($N{=}220$ episode pairs, 20 per type; Table~\\ref{tab:cross-model-detail}).\nThe internal strategy dies in $41.4\\%$ of episodes versus $11.4\\%$ for deterministic (death-rate differential $+30.0$~pp), with 83 deterministic-preferred, 3 internal-preferred (1.4\\%, all death-asymmetry reversals), and 134 no-preference labels.\nBoth models exhibit nearly identical internal vulnerability (${\\sim}$42\\%: Qwen $42.9\\%$, Llama $41.4\\%$), confirming that death-prone failure is empirically dominated by the task environment rather than model-specific factors. The differential magnitude varies ($+26.5$~pp Qwen, $+30.0$~pp Llama) because deterministic strategy safety is model-dependent ($16.3\\%$ vs.\\ $11.4\\%$), but directional consistency is 100\\% (10/10 death-prone tasks in both models).\n\\texttt{identify-life-stages-1} shows cross-model precision matching ($55\\%$/$10\\%$/$+45$~pp in both models).\n\\texttt{find-non-living-thing} shows zero deaths in both models, consistent with its majority-class answer distribution.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lrrrl@{}}\n\\toprule\nTask & Int\\% & Det\\% & $\\Delta$\\,pp & D / I / N \\\\\n\\midrule\nidentify-life-stages-1 & 55 & 10 & +45 & 9 / 0 / 11 \\\\\nfreeze & 45 & 0 & +45 & 9 / 0 / 11 \\\\\ngrow-fruit & 45 & 5 & +40 & 8 / 0 / 12 \\\\\nidentify-life-stages-2 & 45 & 5 & +40 & 8 / 0 / 12 \\\\\nmeasure-melting-point & 50 & 15 & +35 & 9 / 0 / 11 \\\\\nlifespan-longest & 35 & 5 & +30 & 7 / 1 / 12 \\\\\nlifespan-l-then-s & 50 & 20 & +30 & 6 / 0 / 14 \\\\\nchemistry-mix & 45 & 20 & +25 & 5 / 0 / 15 \\\\\ninclined-plane & 45 & 20 & +25 & 6 / 0 / 14 \\\\\nfind-animal & 40 & 25 & +15 & 6 / 2 / 12 \\\\\nfind-non-living-thing & 0 & 0 & 0 & 10 / 0 / 10 \\\\\n\\midrule\n\\textbf{Aggregate} & \\textbf{41.4} & \\textbf{11.4} & \\textbf{+30.0} & \\textbf{83 / 3 / 134} \\\\\n\\bottomrule\n\\end{tabular}}%\n\\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\\Delta$ DR descending.}\n\\label{tab:cross-model-detail}\n\\end{table}\n\n\\paragraph{Cross-model and cross-environment summary.}\nTable~\\ref{tab:cross-model-env} (main text, \\S\\ref{sec:cross-model}) consolidates replication results across model families and environments.\n\n\\section{Failure Mode Analysis}\n\\label{app:failure-modes}\n\nAll 105 internal-strategy deaths (100\\%) are triggered by the same action pattern: \\texttt{focus on [object]}. In ScienceWorld, \\texttt{focus on} is the answer-submission action (equivalent to ``this is my final answer''); the LLM agent systematically misuses it as a general interaction or exploration command, and applies it to irrelevant targets (rooms, doors, inventory items). Each such execution submits an incorrect answer and triggers the $-100$ death penalty. Within death episodes, both strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$); the internal strategy's higher death count (105 vs.\\ 40 for deterministic) reflects how often each strategy enters catastrophic states, not different action selection within those states.\n\nManual inspection identifies four failure categories: (A) no task awareness, where the agent executes \\texttt{focus on} without reading the task; (B) task-aware but lacking action grounding, where the agent correctly identifies the objective but cannot map it to valid action primitives; (D) genuine attempts with execution failure; and (E) initial progress wasted by early errors. Category B dominates: agents demonstrate task comprehension but systematically fail to translate it into correct ScienceWorld actions. This taxonomy was produced by a single annotator; no inter-annotator agreement was computed. The categories are intended as qualitative illustrations, not as formal labels with reliability guarantees.\n\\label{tab:death-taxonomy}\n\n\\paragraph{Representative examples.}\n\\emph{Category A} (no task awareness): In a \\texttt{chemistry-mix} episode, the agent immediately executes \\texttt{focus on kitchen}, \\texttt{focus on door}, \\texttt{focus on inventory} without reading the task, dying on the first \\texttt{focus on} call. \\emph{Category B} (comprehension without grounding): In a \\texttt{lifespan-longest-lived} episode, the agent correctly identifies that it must compare animal lifespans and reasons about which animal lives longest, but then executes \\texttt{focus on oak tree} (a non-animal object in the room) instead of navigating to find the target animal, triggering death.\n\n\\paragraph{Action distribution analysis.}\nFigure~\\ref{fig:death-action-dist} shows the action distribution in death versus non-death episodes for the internal strategy; both are dominated by \\texttt{connect} actions, with \\texttt{focus on} moderately more frequent in death episodes ($5.4\\%$ vs.\\ $3.4\\%$). Crucially, Figure~\\ref{fig:death-comparison} reveals that within death episodes, internal and deterministic strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$). The survival gap (105 vs.\\ 40 deaths) therefore reflects how often each strategy enters catastrophic states, not how it behaves within those states. Among fatal \\texttt{focus on} targets, \\texttt{workshop} remains the most frequent (20.0\\%), followed by \\texttt{inventory} (17.1\\%) and \\texttt{kitchen} (10.5\\%), indicating a systematic object bias rather than random exploration. Figure~\\ref{fig:death-timeline} visualizes the temporal pattern: agents execute long sequences of \\texttt{connect} actions before a terminal \\texttt{focus on} triggers death, typically in the final 1--3 steps.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/death_action_distribution.pdf}\n\\caption{Action distribution for the internal (LLM) strategy in death ($n{=}105$) vs.\\ non-death ($n{=}140$) episodes. Left: full distribution (both dominated by \\texttt{connect}). Right: non-\\texttt{connect} actions zoomed. \\texttt{focus on} is moderately more frequent in death episodes ($5.4\\%$ vs.\\ $3.4\\%$), while non-death episodes show higher rates of observation and object interaction.}\n\\label{fig:death-action-dist}\n\\end{figure}\n\n% Figure moved to main text (\\S\\ref{sec:death-decomp})\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/death_action_comparison.pdf}\n\\caption{Non-\\texttt{connect} action distribution comparison between internal (left) and deterministic (right) strategies. Within death episodes, both strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$); the internal strategy's higher death count (105 vs.\\ 40) reflects more frequent entry into catastrophic states, not different action selection within those states.}\n\\label{fig:death-comparison}\n\\end{figure}\n\n\\section{Grounding Ablation}\n\\label{app:grounding-ablation}\n\nWe test whether directly intervening on the dominant death action (\\texttt{focus on}) eliminates death vulnerability on the 10 death-prone tasks (baseline 48.0\\%, $n{=}200$).\n\n\\paragraph{Prompt warning.} Adding an explicit system prompt (``use \\texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\\% ($\\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\\texttt{identify-life-stages-1}: 35\\%$\\to$50\\%; \\texttt{identify-life-stages-2}: 25\\%$\\to$70\\%), where explicit mention of the dangerous action may have increased its salience.\n\n\\paragraph{Action-space filtering.} Blocking \\texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\\% ($\\Delta = -19$~pp). The zero-passthrough rate suggests \\texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.\n\n\\paragraph{Per-task variation.} Under filtering, \\texttt{identify-life-stages} and \\texttt{inclined-plane} approach deterministic-level safety (${\\sim}$15--20\\% DR), while \\texttt{chemistry-mix} and \\texttt{find-animal} remain at 35--40\\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \\texttt{focus on} to incorrect objects.\n\n\\paragraph{Post-ablation counterfactual decomposition.}\nTo test whether death dominance persists after grounding intervention, we run the full decomposition on matched episodes (183 episodes across 10 death-prone task types, paired by variation index).\nGrounding reduces the internal death rate from 50.3\\% to 35.0\\% ($-15.3$\\,pp), yet $\\geq$93\\% of disambiguating labels still arise from death asymmetry ($\\Delta_\\text{nd} \\approx 0.09$, compared to $0.00$ at baseline).\nInternal-preferred episodes increase from 5 to 23 (grounding helps internal strategy survive more often), but the routing signal remains death-driven rather than score-driven.\nOne task type (\\texttt{identify-life-stages-2}, $n{=}10$) shows a paradoxical increase in death rate (50\\%$\\to$80\\%); this outlier likely reflects the small sample size and task-specific prompt interference rather than a systematic effect.\n\n\\section{Ablation Studies}\n\\label{app:ablations}\n\n\\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\\ref{tab:capacity}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nModel & Step Bal.\\ Acc.\\ (\\%) & Ep.\\ Bal.\\ Acc.\\ (\\%) \\\\\n\\midrule\nQwen3-0.6B & $56.4 \\pm 3.5$ & $50.7 \\pm 2.6$ \\\\\nQwen3-1.7B & $58.2 \\pm 4.0$ & $43.1 \\pm 1.0$ \\\\\nQwen3-4B & $59.2 \\pm 3.5$ & $\\mathbf{59.0 \\pm 1.9}$ \\\\\n\\midrule\nAlways-det & 50.0 & 50.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Capacity scaling: step-level and episode-level balanced accuracy (4 seeds, identical configuration across all scales). Step-level accuracy is flat ($56$--$59\\%$, within seed variance). At episode level, only 4B breaks the random baseline ($59.0\\%$, $p < 0.005$).}\n\\label{tab:capacity}\n\\end{table}\n\nStep-level balanced accuracy is flat across scales ($56$--$59\\%$, within seed variance); step-level discrimination is not capacity-sensitive. At episode level, only 4B breaks the random baseline ($59.0 \\pm 1.9\\%$, $p < 0.005$); 0.6B and 1.7B remain at or below chance. The 1.7B model's below-chance episode-level accuracy ($43.1\\%$) may reflect overfitting to spurious step-level correlations that anti-correlate with episode outcomes; without per-class confusion matrices at this scale, this remains a hypothesis. The dominant explanation across scales is that death avoidance constitutes a task-type-level binary signal that a step-level router cannot exploit efficiently.\n\n\\paragraph{Generative router.} A generative routing model trained with explicit routing labels achieves balanced accuracy of 46.7\\%, confirming that the routing bottleneck is signal-limited, not architecture-limited.\n\n\\paragraph{Leave-one-task-type-out routing.} Under leave-one-task-type-out evaluation, blind routing collapses to always-deterministic (balanced accuracy 50.0\\%); a keyword-based variant achieves 62.9\\% only through task-identity leakage, not genuine routing signal. A guided router evaluated under the same protocol confirms this: without task-type identifiers it achieves chance accuracy (50.0\\%), and leaking task names raises this to 62.9\\%, confirming that the only learnable routing feature is task-type identity.\n\n\\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\\%, episode balanced accuracy 50.0\\%, internal recall 0\\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.\n\n\\paragraph{Reasoning depth.} An ablation comparing chain-of-thought reasoning against direct-answer generation on 6 task types ($n{=}120$ episodes per condition, 6 tasks $\\times$ 20 episodes per task) found no significant difference (Mann--Whitney $p > 0.26$, $|d| \\leq 0.31$) and near-identical death rates (41.8\\% vs.\\ 42.5\\%); reasoning depth does not meaningfully alter internal-mode outcomes.\n\n\\section{Threshold Routing Analysis}\n\\label{sec:threshold-routing}\n\nGiven per-task death risk knowledge, we test whether a simple threshold routing strategy can outperform always-deterministic. For each threshold $t \\in [0, 1]$, we route to internal if the per-task internal death rate $\\leq t$, otherwise to deterministic, and sweep all thresholds to find the optimal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\nStrategy & Mean Score & Death Rate & $\\Delta$ vs Det \\\\\n\\midrule\nAlways-det & $-9.47$ & $0.163$ & $0.00$ \\\\\nOptimal threshold ($t{=}0$) & $-11.03$ & $0.155$ & $-1.56$ \\\\\nAlways-internal & $-39.07$ & $0.429$ & $-29.60$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Death-risk threshold routing analysis on 245 episodes. The optimal threshold routes only \\texttt{find-non-living-thing} (the sole zero-death task) to internal, with all other tasks routed to deterministic. Bootstrap 95\\% CI for the difference: $[-8.87, +5.92]$.}\n\\label{tab:threshold-routing}\n\\end{table}\n\nEven with perfect per-task death risk knowledge, threshold routing cannot outperform always-deterministic. The sole zero-death task achieves higher scores under deterministic (+28.5) than internal (+18.9), leaving no room for a beneficial mixed strategy.\n\n\\section{Practitioner Decision Framework}\n\\label{app:decision-framework}\n\nGiven a new interactive environment, the following three-stage procedure diagnoses whether learned routing adds value over a fixed deterministic strategy.\n\n\\paragraph{Stage 1: Pilot collection (${\\sim}$50 episodes).}\nRun pure-internal and pure-deterministic strategies on a representative sample (${\\sim}$50 episode pairs). Compute the death-rate differential $\\Delta\\text{DR} = \\text{DR}_{\\text{int}} - \\text{DR}_{\\text{det}}$.\n\n\\paragraph{Stage 2: Death dominance check.}\nIf $\\Delta\\text{DR} > 15$~pp, death asymmetry is likely the dominant routing signal. Compute the death-label fraction $f_{\\text{death}}$: the proportion of non-tie routing labels where exactly one strategy dies.\n\n\\paragraph{Stage 3: Decision.}\nIf $f_{\\text{death}} > 75\\%$, the routing signal is death-dominated; a fixed deterministic strategy will match or exceed any learned router. If $f_{\\text{death}} < 50\\%$, diverse routing signals may justify a learned router. Between 50\\%--75\\%, collect additional episodes to reduce estimation noise before committing to router development.\n\n\\paragraph{Retrospective validation.}\nAll four experimental conditions in this paper are correctly classified:\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lrrll@{}}\n\\toprule\nCondition & $\\Delta$DR & $f_{\\text{death}}$ & Prediction & Actual \\\\\n\\midrule\nQwen-7B & +26.5 & 78.9\\% & det-fixed & det wins \\\\\nLlama-8B & +30.0 & $>$75\\% & det-fixed & det wins \\\\\nQwen-72B & +27.8 & $>$75\\% & det-fixed & det wins \\\\\nMATH & +0.5 & 0\\% & router viable & no signal \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Retrospective validation of the decision framework. All four conditions are correctly classified (4/4).}\n\\label{tab:decision-framework}\n\\end{table}\n\nThe framework also predicts the inverted-U relationship between capability and death risk: below ${\\sim}$0.5B parameters, agents rarely reach dangerous states (13.3\\% death rate in a 15-episode pilot), so $\\Delta\\text{DR}$ is low and the framework would not recommend fixed-deterministic. Above ${\\sim}$7B, agents are capable enough to enter catastrophic states but not capable enough to avoid them, producing high $\\Delta\\text{DR}$.\n\n\\paragraph{Threshold calibration.} The thresholds above (15~pp, 75\\%, 50\\%) are illustrative, derived from ScienceWorld's specific reward structure (binary death penalty $P{=}100$, sparse terminal rewards). Environments with graded penalties, dense rewards, or qualitatively different failure modes may require different thresholds. Practitioners should calibrate these boundaries for their specific environment.\n\n\\section{Extended Validation of Excluded Tasks}\n\\label{app:extended-validation}\n\nTo verify that task exclusion does not bias toward death-prone tasks, we collect $n{=}20$ episodes for five representative excluded tasks spanning all exclusion categories (Table~\\ref{tab:extended-val}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcrrrrc}\n\\toprule\nTask & Category & $n$ & Int DR & Det DR & $\\Delta$DR & D/I/N \\\\\n\\midrule\nboil & dev-set & 20 & 55\\% & 25\\% & +30\\,pp & 6/0/14 \\\\\nmelt & dev-set & 20 & 45\\% & 20\\% & +25\\,pp & 7/2/11 \\\\\nfind-living-thing & taxonomic & 20 & 55\\% & 15\\% & +40\\,pp & 10/0/10 \\\\\nuse-thermometer & agent-floor & 20 & 50\\% & 20\\% & +30\\,pp & 7/1/12 \\\\\npower-component & agent-floor & 20 & 50\\% & 15\\% & +35\\,pp & 7/0/13 \\\\\n\\midrule\n\\textit{Mean (5 tasks)} & & 100 & 51.0\\% & 19.0\\% & +32.0\\,pp & 37/3/60 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Extended validation ($n{=}20$) of representative excluded task types. All five tasks confirm death asymmetry; mean $\\Delta$DR $= +32.0$\\,pp is consistent with the $n{=}5$ prescreening estimate for these same tasks (Table~\\ref{tab:excluded-death}).}\n\\label{tab:extended-val}\n\\end{table}\n\nNotably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\\ref{tab:per-task}), indicating that excluded tasks are \\emph{more} death-dominated than included tasks, the opposite of a cherry-picking bias.\n\n\\section{Agent Prompt Templates}\n\\label{app:prompt-templates}\n\nBelow we show the complete prompt templates used for agent interaction in ScienceWorld. Both the internal (ReAct) and deterministic strategies share the same system prompt but differ in the user message template.\n\n\\paragraph{System prompt (shared).} Used for all ScienceWorld agent interactions across both computation modes.\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nYou are an agent interacting with a ScienceWorld text\nenvironment. Your goal is to complete the given task by\nchoosing actions from the available action list.\n\nUse the following format for each step:\nThought: &lt;your reasoning about what to do next>\nAction: &lt;exact action string from the valid actions list>\n\nRules:\n- You MUST choose an action from the valid actions list.\n  Do not invent actions.\n- Think step by step about what physical/scientific\n  process is needed.\n- Pay attention to the current observation for clues\n  about object states.\n\\end{tcblisting}\n\n\\paragraph{Internal (ReAct) user template.} At each step, the agent receives the current observation, valid action list, and recent action history, and must select a single action.\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nCurrent observation:\n{observation}\n\nValid actions:\n{valid_actions_str}\n\nPrevious actions taken: {history_str}\n\nChoose your next action.\n\\end{tcblisting}\n\n\\paragraph{Deterministic candidate generation template.} For the deterministic strategy, the agent generates ranked candidate actions instead of selecting one; these candidates are then evaluated via simulator forking (\\S\\ref{sec:method}).\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nCurrent observation:\n{observation}\n\nValid actions:\n{valid_actions_str}\n\nPrevious actions taken: {history_str}\n\nGenerate the top 3 most promising actions from the valid\nactions list, ranked by how likely they are to make\nprogress on the task. Output exactly 3 actions, one per\nline, in this format:\n1. &lt;action>\n2. &lt;action>\n3. &lt;action>\n\\end{tcblisting}\n\n\\paragraph{Reflexion self-reflection prompt.} After a failed episode, the Reflexion agent (\\S\\ref{sec:agent-improvement}) generates a reflection that is injected into subsequent trial attempts as additional system context.\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nYou just completed an episode in a ScienceWorld text\nenvironment but failed.\n\nTask: {task_name}\nFinal score: {final_score}\nOutcome: {outcome}\nNumber of steps taken: {num_steps}\n\nHere is a summary of your actions:\n{action_summary}\n\nAnalyze why this episode failed and provide a short\nstrategy for the next attempt. Focus on:\n1. What went wrong (wrong sequence, missed key step,\n   dangerous action)?\n2. What should be done differently next time?\n\nKeep your reflection under 200 words.\n\\end{tcblisting}\n\n\\paragraph{Grounding warning (ablation).} The prompt warning condition in the grounding ablation (Appendix~\\ref{app:grounding-ablation}) appends the following to the shared system prompt:\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nCRITICAL SAFETY RULE: The 'focus on [object]' action is\nONLY for submitting your final answer. Do NOT use\n'focus on' to examine, inspect, or interact with objects\nduring exploration. Using 'focus on' on the wrong object\nwill cause irreversible failure. Use 'look at',\n'examine', or 'pick up' instead for exploration.\n\\end{tcblisting}\n\n\\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \\emph{select} one action (ReAct), while the deterministic strategy asks it to \\emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.\n\n\\section{Non-Death Episode Case Study}\n\\label{app:non-death-case-study}\n\nWe illustrate the framework's ability to decompose non-death routing signal using \\texttt{find-non-living-thing}, the only task type with zero deaths and 100\\% non-death labels (\\S\\ref{sec:death-decomp}). Using Gemma-2-9B-it counterfactual episodes ($N{=}20$), 12 episodes show routing preference (9 deterministic-preferred, 3 internal-preferred), confirming the framework detects bidirectional signal independent of death asymmetry.\n\n\\paragraph{Deterministic-preferred: knowledge retrieval advantage.}\nIn Episode~3 (det: 67, int: 0), the internal strategy issues nonsensical \\texttt{connect} actions for 18 consecutive steps (e.g., ``connect air to outside,'' ``connect axe to door to foundry'') without ever identifying a target object; the deterministic strategy correctly focuses on ``orange'' (+58) and opens the kitchen door (+9). In Episode~17 (det: 58, int: 50), both strategies find a valid non-living thing, but the deterministic strategy selects a higher-scoring object (orange, 58\\,pts) versus the internal strategy's choice (fountain, 50\\,pts), illustrating that object selection quality creates routing signal even when both strategies succeed.\n\n\\paragraph{Internal-preferred: semantic reasoning advantage.}\nIn Episode~12 (int: 67, det: 58), the task specifies ``move it to the red box in the living room.'' The deterministic strategy focuses on the red box itself, the destination container, not a separate non-living thing, scoring 58\\,pts. The internal strategy correctly distinguishes target from container, choosing ``orange'' (67\\,pts). This semantic error demonstrates that deterministic pattern-matching can miss task-structure subtleties that internal reasoning captures.\n\nThese cases confirm two properties: (1)~the framework captures non-death routing signal when it exists, and (2)~signal flows in both directions: neither strategy uniformly dominates in death-free tasks.\n\n\\paragraph{Systematic analysis of non-death labels.}\nAll 20 non-death non-tie labels in the primary Qwen2.5-7B analysis originate from \\texttt{find-non-living-thing}, the sole death-free task type. In every other task type, non-tie episodes involve at least one strategy dying. We classify the 20 episodes into three error categories:\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lrrr@{}}\n\\toprule\nError category & Det-pref & Int-pref & Total \\\\\n\\midrule\nHallucination-induced & 8 & 2 & 10 \\\\\nObject selection quality & 6 & 1 & 7 \\\\\nAction selection error & 2 & 1 & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Non-death non-tie episode classification. Hallucination-induced: agent's state model is incorrect (e.g., believing \\texttt{eat} completes the task). Object selection quality: both strategies succeed but choose different-value objects. Action selection: correct state model but suboptimal action sequences.}\n\\label{tab:non-death-taxonomy}\n\\end{table}\n\n\\noindent Hallucination-induced errors dominate (50\\%), driven by a recurring ``eat before focus'' pattern: the internal strategy consumes the target object (destroying it) before attempting the scoring action (\\texttt{focus on}), indicating an incorrect state model that equates eating with task completion (11 of 20 episodes). Object selection quality accounts for 35\\%: typically the deterministic strategy selecting ``orange'' (58\\,pts) while the internal strategy settles for lower-value objects (``fountain'' or ``picture,'' 50\\,pts). The error categories are bidirectional: 2 of 10 hallucination episodes and 1 of 3 action selection episodes are internal-preferred, confirming the framework detects failures in both strategies. Score gaps reflect category severity: hallucination errors produce large gaps ($17$--$67$\\,pts, one strategy scores zero) while object selection differences produce small gaps ($8$--$9$\\,pts, both strategies functional).\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting \\LaTeX{}.\n    \\item \\textbf{Literature:} summarizing related papers to inform the related-work section.\n\\end{itemize}\n\n\\end{document}\n",
      "numLines": 803,
      "startLine": 1,
      "totalLines": 803
    }
  },
  "sourceToolAssistantUUID": "188795a4-3eda-4a9a-acd5-4b9319c5bd1d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-25T15:16:42.579Z_

<details open><summary>🔧 Tool call — Read · `toolu_019gTtSHXnspfo7kNkbFKohx`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0f9807a2-6fa2-4d8f-8ce8-02e7b209f851",
  "isSidechain": false,
  "requestId": "req_011CbPWRtJ5FFZK349w5Wr85",
  "type": "assistant",
  "uuid": "2d816c0b-f58e-4b11-8466-f64d6679f6dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01363jruHhnNBb3pAVcF2cLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 38727,
      "output_tokens": 721,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11965,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 721,
          "cache_read_input_tokens": 38727,
          "cache_creation_input_tokens": 11965,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11965
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

_source line 38 · 2026-05-25T15:16:44.164Z_

```json
{
  "parentUuid": "d710b15e-4479-4d7a-83a3-889e7d70420a",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "8c70b897-a08c-470c-9a1d-3544e2d5cb83",
  "timestamp": "2026-05-25T15:16:44.164Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
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
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 21 warnin…",
  "leafUuid": "8c70b897-a08c-470c-9a1d-3544e2d5cb83",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Runtime record

_source line 40_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit for simgate-modular-routing",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Assistant

_source line 41 · 2026-05-25T15:16:48.368Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have read all the tex files. Let me also check for some specific patterns mentioned in the audit dimensions. Let me do some targeted searches for AI style issues, em-dashes, filler words, etc.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8c70b897-a08c-470c-9a1d-3544e2d5cb83",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "8249b92b-2b62-4b5f-b2b0-6a724613dd52",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 42 · 2026-05-25T15:16:49.399Z_

现在执行正则级扫描，检查 AI 风格标志和其他具体 pattern。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8249b92b-2b62-4b5f-b2b0-6a724613dd52",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "0098c844-5645-4200-a163-f4f2fd5c5ae1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 43 · 2026-05-25T15:16:51.818Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01DCrJ8ijnm5h6HN9kqF9kXx`</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0098c844-5645-4200-a163-f4f2fd5c5ae1",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "a232e9f6-aea4-4155-a056-3ee6858d4fc2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 44 · 2026-05-25T15:16:58.296Z_

<details><summary>↩ Tool result · `toolu_013uVMh7o33G3wGs3XW1kYHt`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:162:\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\ $\Delta_{\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1434d05e-ce95-4f50-8806-62373a65a00b",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "becdf737-1e59-412c-b98a-b2c95960ea8c",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:162:\\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\\ $\\Delta_{\\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "1434d05e-ce95-4f50-8806-62373a65a00b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 45 · 2026-05-25T15:16:51.852Z_

<details><summary>↩ Tool result · `toolu_01DCrJ8ijnm5h6HN9kqF9kXx`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a232e9f6-aea4-4155-a056-3ee6858d4fc2",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "d99d3561-e166-4514-aba0-5b1f107ac375",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "a232e9f6-aea4-4155-a056-3ee6858d4fc2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 46 · 2026-05-25T15:16:52.783Z_

<details open><summary>🔧 Tool call — Grep · `toolu_016ocH72qG1Rwz2JPtRouZGG`</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d99d3561-e166-4514-aba0-5b1f107ac375",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "35fd18a5-bdca-4c07-be90-8170b4d474f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 47 · 2026-05-25T15:16:52.797Z_

<details><summary>↩ Tool result · `toolu_016ocH72qG1Rwz2JPtRouZGG`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "35fd18a5-bdca-4c07-be90-8170b4d474f0",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "43f66782-31fd-4d77-b31a-3a4b67330c41",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "35fd18a5-bdca-4c07-be90-8170b4d474f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 48 · 2026-05-25T15:16:53.739Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01D8ANdegGyMWv23fDTSr9CL`</summary>

```json
{
  "pattern": "---",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "43f66782-31fd-4d77-b31a-3a4b67330c41",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "8ee5df56-2fcf-4ea9-b301-7a0645974785",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 49 · 2026-05-25T15:16:53.759Z_

<details><summary>↩ Tool result · `toolu_01D8ANdegGyMWv23fDTSr9CL`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:4:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:65:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:85:Qwen2.5-7B & MATH & 795 & --- & --- & --- & --- & none \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:100:(none, full) & 245 & 78.9 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:138:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:183:Exact permutation ($2{,}048$ perms) & $0.002$ & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:184:Sign test & $< 0.001$ & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:348:Always-det & --- & --- & 50.0 \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:9:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:12:Always-deterministic matches 96.3\% of oracle decisions (\S\ref{sec:baselines}), capping routing's marginal value at 2.89 points---an \emph{oracle degeneracy} where perfect per-episode foresight provides negligible benefit over a trivial baseline, because $\Delta_{\text{nd}} = 2.84$ (9.6\% of total gap).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:13:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:16:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:41:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:11:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:15:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8ee5df56-2fcf-4ea9-b301-7a0645974785",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "e6aeeb3c-df10-4c0d-9bf9-d242c376ad1a",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:4:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:65:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:85:Qwen2.5-7B & MATH & 795 & --- & --- & --- & --- & none \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:100:(none, full) & 245 & 78.9 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:138:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:183:Exact permutation ($2{,}048$ perms) & $0.002$ & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:184:Sign test & $< 0.001$ & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:348:Always-det & --- & --- & 50.0 \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:9:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:12:Always-deterministic matches 96.3\\% of oracle decisions (\\S\\ref{sec:baselines}), capping routing's marginal value at 2.89 points---an \\emph{oracle degeneracy} where perfect per-episode foresight provides negligible benefit over a trivial baseline, because $\\Delta_{\\text{nd}} = 2.84$ (9.6\\% of total gap).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:13:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:16:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:41:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:11:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:15:[Omitted long matching line]",
    "numLines": 16
  },
  "sourceToolAssistantUUID": "8ee5df56-2fcf-4ea9-b301-7a0645974785",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 50 · 2026-05-25T15:16:55.704Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01NzstcZyHD4HbPg77LD3mhE`</summary>

```json
{
  "pattern": "it is worth noting|notably|importantly|furthermore|moreover|additionally",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true,
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6aeeb3c-df10-4c0d-9bf9-d242c376ad1a",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "0fd6e2b5-0970-42ab-9471-53557eed349d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 51 · 2026-05-25T15:16:55.720Z_

<details><summary>↩ Tool result · `toolu_01NzstcZyHD4HbPg77LD3mhE`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:651:Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\ref{tab:per-task}), indicating that excluded tasks are \emph{more} death-dominated than included tasks, the opposite of a cherry-picking bias.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0fd6e2b5-0970-42ab-9471-53557eed349d",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "71987a0e-6f84-462b-a406-09edad03791a",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:651:Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\\ref{tab:per-task}), indicating that excluded tasks are \\emph{more} death-dominated than included tasks, the opposite of a cherry-picking bias.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "0fd6e2b5-0970-42ab-9471-53557eed349d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-25T15:16:56.688Z_

<details open><summary>🔧 Tool call — Grep · `toolu_016DwiW94MPVr6o1dqZLLjVY`</summary>

```json
{
  "pattern": "ing,|ing\\.",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "71987a0e-6f84-462b-a406-09edad03791a",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "5fb83ad5-df98-4362-9a67-2e1cb660291d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 53 · 2026-05-25T15:16:56.703Z_

<details><summary>↩ Tool result · `toolu_016DwiW94MPVr6o1dqZLLjVY`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:3:\paragraph{Tool-Augmented Agents and Adaptive Routing.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:7:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:7:\caption{Per-task death rate differential vs.\ performance gap ($n{=}11$ task types). The near-perfect correlation ($r = 0.97$) is a structural consequence of death dominance (DAF $\to 1 \Rightarrow r \to 1$), not an independent finding. The sole outlier (\texttt{find-non-living-thing}, diamond marker) has zero deaths; its $\Delta_{\text{full}} = +9.58$ arises entirely from non-death score differences.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:57:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:148:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:88:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:95:\paragraph{Task selection and anti-cherry-picking.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:191:\noindent All methods confirm significance with $p < 0.01$, and the 95\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:333:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:389:\caption{Pearson $r$ between per-task death-rate differential and $\Delta_{\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \textsuperscript{*}Default ScienceWorld setting.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:437:\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\Delta_{\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\Delta_{\text{full}}$ descending.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:476:\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\Delta$ DR descending.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:488:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:518:\paragraph{Prompt warning.} Adding an explicit system prompt (``use \texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\% ($\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\texttt{identify-life-stages-1}: 35\%$\to$50\%; \texttt{identify-life-stages-2}: 25\%$\to$70\%), where explicit mention of the dangerous action may have increased its salience.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:520:\paragraph{Action-space filtering.} Blocking \texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\% ($\Delta = -19$~pp). The zero-passthrough rate suggests \texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:522:\paragraph{Per-task variation.} Under filtering, \texttt{identify-life-stages} and \texttt{inclined-plane} approach deterministic-level safety (${\sim}$15--20\% DR), while \texttt{chemistry-mix} and \texttt{find-animal} remain at 35--40\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \texttt{focus on} to incorrect objects.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:533:\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\ref{tab:capacity}).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:557:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:559:\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\%, episode balanced accuracy 50.0\%, internal recall 0\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:756:\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \emph{select} one action (ReAct), while the deterministic strategy asks it to \emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:764:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:767:In Episode~12 (int: 67, det: 58), the task specifies ``move it to the red box in the living room.'' The deterministic strategy focuses on the red box itself, the destination container, not a separate non-living thing, scoring 58\,pts. The internal strategy correctly distinguishes target from container, choosing ``orange'' (67\,pts). This semantic error demonstrates that deterministic pattern-matching can miss task-structure subtleties that internal reasoning captures.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:772:All 20 non-death non-tie labels in the primary Qwen2.5-7B analysis originate from \texttt{find-non-living-thing}, the sole death-free task type. In every other task type, non-tie episodes involve at least one strategy dying. We classify the 20 episodes into three error categories:
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:797:    \item \textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:57:Yes. We specify vLLM for inference, LoRA for fine-tuning, and provide all relevant configuration parameters (Table~\ref{tab:hyperparams}). Model identifiers are given precisely (e.g., Qwen2.5-7B-Instruct, Qwen3-1.7B).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:76:Yes. Claude (Anthropic) was used for code development, data analysis scripting, and manuscript drafting. All experimental design, scientific claims, and interpretation of results were conducted by the authors.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:24:\captionof{table}{Sensitivity of DAF to death penalty magnitude $P$. $\Delta_{\text{nd}} = 2.84$ is invariant; as $P$ increases, $\Delta_{\text{full}} \approx \delta P + \Delta_{\text{nd}}$ grows, mechanically increasing DAF. \textsuperscript{*}Default ScienceWorld setting. Bootstrap 95\% CIs ($B{=}10{,}000$).}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:61:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5fb83ad5-df98-4362-9a67-2e1cb660291d",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "983aecac-6ab2-4ee3-bd31-1f7494352d3f",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:3:\\paragraph{Tool-Augmented Agents and Adaptive Routing.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:7:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:7:\\caption{Per-task death rate differential vs.\\ performance gap ($n{=}11$ task types). The near-perfect correlation ($r = 0.97$) is a structural consequence of death dominance (DAF $\\to 1 \\Rightarrow r \\to 1$), not an independent finding. The sole outlier (\\texttt{find-non-living-thing}, diamond marker) has zero deaths; its $\\Delta_{\\text{full}} = +9.58$ arises entirely from non-death score differences.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:57:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:148:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:88:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:95:\\paragraph{Task selection and anti-cherry-picking.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:191:\\noindent All methods confirm significance with $p < 0.01$, and the 95\\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:333:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:389:\\caption{Pearson $r$ between per-task death-rate differential and $\\Delta_{\\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \\geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \\textsuperscript{*}Default ScienceWorld setting.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:437:\\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\\Delta_{\\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\\Delta_{\\text{full}}$ descending.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:476:\\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\\Delta$ DR descending.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:488:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:518:\\paragraph{Prompt warning.} Adding an explicit system prompt (``use \\texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\\% ($\\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\\texttt{identify-life-stages-1}: 35\\%$\\to$50\\%; \\texttt{identify-life-stages-2}: 25\\%$\\to$70\\%), where explicit mention of the dangerous action may have increased its salience.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:520:\\paragraph{Action-space filtering.} Blocking \\texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\\% ($\\Delta = -19$~pp). The zero-passthrough rate suggests \\texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:522:\\paragraph{Per-task variation.} Under filtering, \\texttt{identify-life-stages} and \\texttt{inclined-plane} approach deterministic-level safety (${\\sim}$15--20\\% DR), while \\texttt{chemistry-mix} and \\texttt{find-animal} remain at 35--40\\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \\texttt{focus on} to incorrect objects.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:533:\\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\\ref{tab:capacity}).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:557:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:559:\\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\\%, episode balanced accuracy 50.0\\%, internal recall 0\\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:756:\\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \\emph{select} one action (ReAct), while the deterministic strategy asks it to \\emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:764:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:767:In Episode~12 (int: 67, det: 58), the task specifies ``move it to the red box in the living room.'' The deterministic strategy focuses on the red box itself, the destination container, not a separate non-living thing, scoring 58\\,pts. The internal strategy correctly distinguishes target from container, choosing ``orange'' (67\\,pts). This semantic error demonstrates that deterministic pattern-matching can miss task-structure subtleties that internal reasoning captures.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:772:All 20 non-death non-tie labels in the primary Qwen2.5-7B analysis originate from \\texttt{find-non-living-thing}, the sole death-free task type. In every other task type, non-tie episodes involve at least one strategy dying. We classify the 20 episodes into three error categories:\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:797:    \\item \\textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:57:Yes. We specify vLLM for inference, LoRA for fine-tuning, and provide all relevant configuration parameters (Table~\\ref{tab:hyperparams}). Model identifiers are given precisely (e.g., Qwen2.5-7B-Instruct, Qwen3-1.7B).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:76:Yes. Claude (Anthropic) was used for code development, data analysis scripting, and manuscript drafting. All experimental design, scientific claims, and interpretation of results were conducted by the authors.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:24:\\captionof{table}{Sensitivity of DAF to death penalty magnitude $P$. $\\Delta_{\\text{nd}} = 2.84$ is invariant; as $P$ increases, $\\Delta_{\\text{full}} \\approx \\delta P + \\Delta_{\\text{nd}}$ grows, mechanically increasing DAF. \\textsuperscript{*}Default ScienceWorld setting. Bootstrap 95\\% CIs ($B{=}10{,}000$).}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:61:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]",
    "numLines": 29
  },
  "sourceToolAssistantUUID": "5fb83ad5-df98-4362-9a67-2e1cb660291d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-25T15:16:58.282Z_

<details open><summary>🔧 Tool call — Grep · `toolu_013uVMh7o33G3wGs3XW1kYHt`</summary>

```json
{
  "pattern": "delve|leverage|utilize|facilitate|myriad|plethora",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true,
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "983aecac-6ab2-4ee3-bd31-1f7494352d3f",
  "isSidechain": false,
  "requestId": "req_011CbPWSc62X2iP5DTA32Dvd",
  "type": "assistant",
  "uuid": "1434d05e-ce95-4f50-8806-62373a65a00b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E9CvMi1bGCgmhJKhSTHrvX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37207,
      "cache_read_input_tokens": 50692,
      "output_tokens": 1008,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37207,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1008,
          "cache_read_input_tokens": 50692,
          "cache_creation_input_tokens": 37207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37207
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

_source line 55_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 21 warnin…",
  "leafUuid": "becdf737-1e59-412c-b98a-b2c95960ea8c",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Runtime record

_source line 56_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit for simgate-modular-routing",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Assistant

_source line 57 · 2026-05-25T15:20:04.043Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me check abstract word count and look for some more patterns. Let me also count the --- (em-dash in LaTeX) occurrences more carefully.

Looking at the `---` results, there are several LaTeX em-dashes used in the text. These are `---` which render as em-dashes (—). Let me enumerate them:

1. abstract.tex:2 - "routing---deciding..." - em-dash in abstract
2. introduction.tex:11 - "methods---whether inserting..." - em-dash
3. introduction.tex:15 - multiple `---` 


4. experiments.tex:65, 85, 100, 138 - some in tables and some in text
5. discussion.tex:9, 12, 13, 16 - em-dashes in text
6. method.tex:41 - em-dash in text

Now I need to check for a separate Limitations section in the appendix, which would violate EMNLP guidelines, and verify the abstract word count. From what I've found so far, the Limitations section appears in main.tex around line 43-44 as a section marker.

Looking more carefully at the structure, I see the Limitations section is in the main text, which is correct. However, the responsibleNLPchecklist.tex references an Ethics Statement that should follow the Limitations, but I'm not finding it in main.tex. After the Limitations section, the file goes directly to the bibliography and appendix without an Ethics Statement section visible, which could be an issue if the checklist expects one.

Now checking the abstract length—it appears to be cut off mid-sentence, but I can see it covers the core contribution about the counterfactual framework for routing signal decomposition in ScienceWorld, showing how death asymmetry accounts for most routing decisions across different model scales. The pattern holds across different model scales, with death avoidance explaining the entire performance gap between the two strategies. Always-deterministic routing captures 96.3% of the oracle's decisions, which means there's barely any room for a learned router to improve beyond that. Boundary tests on MATH and ALFWorld show the framework can identify fundamentally different routing mechanisms, including cases where no routing signal is present at all.

Now I'm checking whether the abstract stays within the 200-word limit. It looks like I'm around 140-150 words excluding the footnote, so there's comfortable headroom. Let me verify the narrative consistency across the abstract and introduction to make sure the problem statement and contributions align properly.

The abstract frames the core issue as routing—deciding when to use internal reasoning versus external computation—and notes that existing methods train routers without first understanding what signal drives the routing preference. The introduction presents the same problem: current routing approaches assume the signal comes from diverse sources, but we should diagnose the mechanistic signal before training. These align well.

Looking at the contributions listed in the introduction, I have three main claims: the episode-level counterfactual diagnostic framework with the DAF metric, evidence that routing signal in ScienceWorld is death-dominated, and boundary probes across MATH and ALFWorld. Scanning through the method sections, the episode-level counterfactual collection and DAF metric appear in sections 3.1-3.4, the death decomposition and multi-model validation in 4.1-4.2, and the cross-environment boundary probes in 4.4. The method also includes agent improvement baselines and router training experiments that extend these contributions. Everything maps back to the stated contributions, so the structure holds together.

The design choice for episode-level oracle labeling makes sense given that per-step labeling degenerates under sparse terminal rewards—this justifies why we need the episode-level approach rather than simpler alternatives.

Now checking whether the experiments actually verify what the introduction claims: the framework and DAF metric are demonstrated in section 4.1, the death-dominated finding is shown across 4.1-4.3 with multiple model families, and the boundary probes are in 4.4. The conclusion then summarizes these findings—78.9% of non-tie labels trace to death asymmetry, consistency across model families, and the observation that deterministic approaches match oracle performance. The narrative flows from problem identification through diagnosis to validation across environments.

Looking at the finer details now: the abstract claims three model families spanning 7B to 70B, and the experiments cover Qwen2.5-7B, Llama-3.1-8B, and Gemma-2-9B at the smaller scale, plus Qwen2.5-72B and Llama-70B at 70B scale—so that's accurate. The claim about death avoidance accounting for the entire performance gap at larger scale checks out with the 92.4-101.0% numbers for 70B models. And the boundary probes on MATH and ALFWorld do show what the abstract promises: MATH has no routing signal while ALFWorld exhibits information asymmetry, confirming the framework can distinguish different routing mechanisms.

One thing I'm noticing though—the abstract and intro frame this as an "episode-level counterfactual diagnostic framework," but there's also a practical decision framework for practitioners tucked in Appendix R. The second contribution mentions that roughly 50 episodes suffice for practitioners to apply this, which is solid, though it's more of an implementation detail than a core methodological contribution.

Now checking the chapter structure. The abstract does answer the four key questions: what's the problem (routing signals), what's the method (counterfactual framework), what are the results (78.9% death avoidance), and why it matters (learned routing isn't necessary). The intro follows a five-paragraph arc starting with background on how deployed language models need to make routing decisions repeatedly, then moving into the proposed counterfactual diagnostic approach.

Looking at the actual intro paragraphs though, it's more compressed than a strict five-paragraph structure—the first paragraph weaves together background, existing methods, and the implicit assumption that needs questioning. The second paragraph introduces the framework and design decision around episode-level analysis. The third covers the results from ScienceWorld with cross-model validation. It's lean but covers all the necessary elements, though the "problem importance" angle is somewhat woven in rather than explicit.

The Related Work section uses thematic groupings with `\paragraph{}` headers rather than chronological listing, which works well for a diagnostics paper. The first paragraph is dense with many citations but does attempt some organization around tool augmentation methods, task decomposition, and RL-based selection. I should check whether the subsequent paragraphs maintain this thematic clarity or if they become more scattered.

Now I'm mapping each contribution to its corresponding sections. The counterfactual diagnostic framework and DAF metric are covered in the methods section, the routing signal analysis appears across multiple tables in the results, and the boundary probes are in section 4.4. The orphan sections like baselines and router training both support the second contribution about oracle degeneracy and learned routing behavior.

The title and abstract align well with the actual content—five models across three families at two scales, and the core claim about death avoidance driving 78.9% of routing decisions is directly supported by the data with confidence intervals. I should verify that "significantly" is properly substantiated throughout. The "suffices" framing is a bit strong given it's based on retrospective validation of the same dataset. Moving to experimental rigor, the paper does well on error bars with bootstrap confidence intervals and comparisons against recent baselines like ReAct, Reflexion, and LATS. The ablations are thorough—covering penalty sensitivity, cross-model and cross-environment generalization, router training variants, and several other dimensions—which is impressive given the method has just two core components.

On reproducibility, I'm noticing the counterfactual collection relies on a single seed with one replication, though they do provide confidence bounds. The router training uses 4 seeds which is reasonable, and they've documented hyperparameters in the appendix along with GPU requirements and prompt templates. One thing that stands out is the Ethics Statement is mentioned in the checklist but I'm not seeing it in the main text.

For terminology, the notation is consistent throughout—$\Delta_{\text{full}}$ and $\Delta_{\text{nd}}$ for score gaps, DAF and $\delta$ for the differential metrics, and SCI for the concentration index. Though I'm spotting a labeling issue in Table 6 where the column header says "DAF (%)" but the values actually represent the label fraction rather than the DAF metric itself, which creates some confusion. score-based) vs. 78.9% (label-based) are different numbers. Let me re-read...

Actually, looking at the table caption: "Leave-one-task-out DAF sensitivity (label fraction)." So DAF here refers to the label fraction, not the score-based DAF. But the column header says "DAF (%)" which is ambiguous. In the main text, DAF is defined as the score-based metric (§3.4), but "label fraction" is separate. The full dataset row shows 78.9% — that's the label fraction, not DAF (which is 90.4%).

So there's a terminology mismatch: the table labels the column "DAF (%)" but it's actually showing label fractions, while the paper distinguishes between these two metrics elsewhere. This is a clear inconsistency that could confuse readers.

Now looking at the chapter transitions, the flow from Abstract through Introduction and into Related Work feels natural, and the progression into Method and then Experiments follows the standard structure. The text mentions how the diagnostic framework quantifies what drives routing signal, which bridges the methodology into the empirical work.

The Discussion goes beyond just restating numbers — it interprets signal granularity, failure mechanisms, oracle degeneracy, and practical implications. That's good.

For limitations, the paper acknowledges that the quantitative validation is specific to ScienceWorld while MATH and ALFWorld are just boundary probes. It also notes that DAF depends on a fixed death penalty and would need extensions for graded or stochastic failure. The baseline comparison uses single-pass ReAct, which is a limitation for more aggressive baselines. I'm verifying this against the user's stated requirements — they want just a short paragraph covering around 3 points, which this satisfies. The audit template defaults to 150+ words and 2+ limitations, but the user's rule takes precedence here, so the current length is appropriate. Now I'm noticing the writing style uses em-dashes consistently throughout the document for clause separation.

Let me count these more carefully across the sections. The LaTeX `---` syntax appears multiple times in the abstract, introduction, method, and discussion sections. The paper-writing norms explicitly require removing all em-dashes, so this is a significant style violation I need to flag. I'm going through each occurrence to document where they appear and confirm they're not just table formatting artifacts. Now I'm checking the abstract word count more carefully. The opening sentences about LLM agent routing and the counterfactual framework come to around 50 words combined, and I'm partway through examining how the ScienceWorld results break down the routing mechanisms, particularly the death asymmetry finding that accounts for most of the non-tie labels.

Continuing through the rest of the abstract, the replication across model scales and the comparison to oracle routing decisions add another 40 words or so, and the boundary probes on other environments bring it to roughly 140 words total—comfortably under the 200-word limit. The footnote about code availability is a bit unconventional but shouldn't be a blocker. For the limitations section, I see there's one in the main text, which satisfies the requirement.

Now checking whether the responsible NLP checklist is actually included in the compiled PDF—I'm looking at the main.tex structure and the checklist file exists but isn't being input into the document, so it won't appear in the submission unless I add that reference.

Actually, I'm noticing the checklist mentions an Ethics Statement that should come after the Limitations section, but there's no such section in the current PDF. Since the checklist is meant for the OpenReview form rather than the paper itself, this might not be an issue, though I should verify whether EMNLP 2026 requires an ethics section as part of the paper.

Looking at the page count now—the document is currently at 22 pages total, and I need to check this against EMNLP's requirements. Limitations section is minimal at around 0.15 pages, bringing the main text to roughly 7-8 pages total—tight but likely within the 8-page limit given the two-column format and dense figures/tables. Since Phase 1 didn't flag page count issues, I'll mark this as verified.

I'm also noticing a few other problems: the checklist claims an Ethics Statement exists but it's not in the main.tex file, though EMNLP typically makes this optional so it might not be a blocker. More concerning is the Table 6 column header mismatch where the "DAF (%)" column appears to show label fractions rather than the actual score-based DAF values.

There's also inconsistent terminology around DAF itself—the definition in §3.4 treats it as a score-based metric (90.4%), but Table 6 and §4.1 seem to use it for label fractions (78.9%), which creates ambiguity about what's actually being measured.

The claim that "a ~50-episode pilot suffices" for Contribution 2 is overstated given it's only validated retrospectively on 4 conditions in this paper. And the discussion's assertion that "death vulnerability is a task-environment property" appears to be cut off mid-thought.

Actually, looking at the full statement: the paper frames this as a strong causal claim derived from correlation, where 5 converging models suggest a pattern but "environment property" is quite a strong characterization. The text does hedge with "provides evidence that," but the section heading itself uses the unqualified "task-environment property" language directly.

On reproducibility, vLLM v0.21.0 is noted as potentially a future version relative to my training data cutoff, which is worth flagging. And checking the introduction for cold references—concepts like "episode-level counterfactual diagnostic framework" and "Death Avoidance Factor (DAF)" are introduced before use, though I should verify the exact placement of the DAF definition relative to its first mention.

Looking at contribution (2) in the introduction, it actually bundles two separate ideas: the empirical finding about death-dominance in routing signals (78.9% of non-tie labels), and a practitioner-facing decision framework for assessing whether learned routing adds value. These feel like distinct contributions packaged together, which is reasonable but worth noting.

Now I'm checking the responsible NLP checklist against what's actually in the paper. The checklist claims there's an Ethics Statement after the Limitations section, but scanning through main.tex, I only see the Limitations section followed directly by the bibliography and appendix—no Ethics Statement exists. The checklist also references computational costs being reported, but I don't see that either. This is a mismatch between what the checklist declares and what's actually present in the document. Now I'm checking the EMNLP requirements more carefully — ethics statements are optional, so if the paper doesn't include one, that's fine, but the checklist shouldn't claim it exists. I'm also noticing a potential labeling issue in Table 6 where the caption mentions label fraction but the column header says "DAF (%)", which could be confusing about what's actually being measured. The paper's terminology is genuinely ambiguous—DAF has a formal definition based on scores, but the label fraction is also presented as a diagnostic metric, and they're used somewhat interchangeably in places like Table 6. I should flag this as a potential source of confusion for readers rather than treating it as a clear error.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "becdf737-1e59-412c-b98a-b2c95960ea8c",
  "isSidechain": false,
  "requestId": "req_011CbPWTm542NQi2JVvnE3Rq",
  "type": "assistant",
  "uuid": "762a4f75-e4d7-4e3d-8cbd-7dc081b01c49",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E7oNVRLoX6Qe3ur2fvaxDH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5042,
      "cache_read_input_tokens": 87899,
      "output_tokens": 8961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5042,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8961,
          "cache_read_input_tokens": 87899,
          "cache_creation_input_tokens": 5042,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5042
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

_source line 58 · 2026-05-25T15:20:04.044Z_

现在检查 abstract 字数和一些其他细节。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "762a4f75-e4d7-4e3d-8cbd-7dc081b01c49",
  "isSidechain": false,
  "requestId": "req_011CbPWTm542NQi2JVvnE3Rq",
  "type": "assistant",
  "uuid": "63c24a4a-59c4-436e-a04a-d038cd7ed1a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E7oNVRLoX6Qe3ur2fvaxDH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5042,
      "cache_read_input_tokens": 87899,
      "output_tokens": 8961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5042,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8961,
          "cache_read_input_tokens": 87899,
          "cache_creation_input_tokens": 5042,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5042
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

_source line 59 · 2026-05-25T15:20:06.610Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01ExJPPp85WUP1FAXNnZKPpW`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper && cat abstract.tex | sed 's/\\\\[a-zA-Z]*{[^}]*}//g; s/\\\\[a-zA-Z]*//g; s/[{}~]/ /g; s/\\\\//g; s/  */ /g; s/begin{abstract}//; s/end{abstract}//' | tr -s ' ' '\\n' | grep -v '^$' | wc -l",
  "description": "Rough word count for abstract"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63c24a4a-59c4-436e-a04a-d038cd7ed1a3",
  "isSidechain": false,
  "requestId": "req_011CbPWTm542NQi2JVvnE3Rq",
  "type": "assistant",
  "uuid": "18251729-746d-4993-bf57-0f9e6fb37a31",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E7oNVRLoX6Qe3ur2fvaxDH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5042,
      "cache_read_input_tokens": 87899,
      "output_tokens": 8961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5042,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8961,
          "cache_read_input_tokens": 87899,
          "cache_creation_input_tokens": 5042,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5042
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

_source line 60 · 2026-05-25T15:20:09.595Z_

<details><summary>↩ Tool result · `toolu_01H34NZiw5mgpr9yLJ1PEJf7`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5d25ad4c-5573-4ec4-95d7-83411ec1109a",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "6e378644-c4c7-41c6-ab8f-904a367b5295",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "5d25ad4c-5573-4ec4-95d7-83411ec1109a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 61 · 2026-05-25T15:20:06.818Z_

<details><summary>↩ Tool result · `toolu_01ExJPPp85WUP1FAXNnZKPpW`</summary>

```text
137
Shell cwd was reset to /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "18251729-746d-4993-bf57-0f9e6fb37a31",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "7c2d48c2-334b-47a2-8706-f92776ab0b14",
  "toolUseResult": {
    "stdout": "137",
    "stderr": "\nShell cwd was reset to /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "18251729-746d-4993-bf57-0f9e6fb37a31",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 62 · 2026-05-25T15:20:07.251Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01NZEXLKazxP2nN8pJ3ZJqUH`</summary>

```json
{
  "pattern": "\\\\section\\*?\\{",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7c2d48c2-334b-47a2-8706-f92776ab0b14",
  "isSidechain": false,
  "requestId": "req_011CbPWTm542NQi2JVvnE3Rq",
  "type": "assistant",
  "uuid": "914e5fae-15b9-49f5-a637-280c8ba74b27",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E7oNVRLoX6Qe3ur2fvaxDH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5042,
      "cache_read_input_tokens": 87899,
      "output_tokens": 8961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5042,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8961,
          "cache_read_input_tokens": 87899,
          "cache_creation_input_tokens": 5042,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5042
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

_source line 63 · 2026-05-25T15:20:07.263Z_

<details><summary>↩ Tool result · `toolu_01NZEXLKazxP2nN8pJ3ZJqUH`</summary>

```text
43:\section*{Limitations}
73:\section{Signal Concentration Index}
85:\section{Labeling Quality Audit}
90:\section{Per-Task Decomposition}
137:\section{Correlation Robustness}
166:\section{Cluster Bootstrap Sensitivity Analysis}
195:\section{Per-Task Death Rate Confidence Intervals}
202:\section{Leave-One-Task-Out DAF Sensitivity}
207:\section{Per-Task Dose-Response Breakdown}
239:\section{Router Training Details}
279:\section{Seed Robustness}
363:\section{Penalty Sensitivity Analysis}
395:\section{Cross-Environment Details}
444:\section{Cross-Model Verification}
483:\section{Failure Mode Analysis}
513:\section{Grounding Ablation}
530:\section{Ablation Studies}
563:\section{Threshold Routing Analysis}
587:\section{Practitioner Decision Framework}
625:\section{Extended Validation of Excluded Tasks}
653:\section{Agent Prompt Templates}
758:\section{Non-Death Episode Case Study}
792:\section{Use of AI Assistants}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "914e5fae-15b9-49f5-a637-280c8ba74b27",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "02ae6990-6874-4e1a-b520-8dfb863e8acf",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "43:\\section*{Limitations}\n73:\\section{Signal Concentration Index}\n85:\\section{Labeling Quality Audit}\n90:\\section{Per-Task Decomposition}\n137:\\section{Correlation Robustness}\n166:\\section{Cluster Bootstrap Sensitivity Analysis}\n195:\\section{Per-Task Death Rate Confidence Intervals}\n202:\\section{Leave-One-Task-Out DAF Sensitivity}\n207:\\section{Per-Task Dose-Response Breakdown}\n239:\\section{Router Training Details}\n279:\\section{Seed Robustness}\n363:\\section{Penalty Sensitivity Analysis}\n395:\\section{Cross-Environment Details}\n444:\\section{Cross-Model Verification}\n483:\\section{Failure Mode Analysis}\n513:\\section{Grounding Ablation}\n530:\\section{Ablation Studies}\n563:\\section{Threshold Routing Analysis}\n587:\\section{Practitioner Decision Framework}\n625:\\section{Extended Validation of Excluded Tasks}\n653:\\section{Agent Prompt Templates}\n758:\\section{Non-Death Episode Case Study}\n792:\\section{Use of AI Assistants}",
    "numLines": 23
  },
  "sourceToolAssistantUUID": "914e5fae-15b9-49f5-a637-280c8ba74b27",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 64 · 2026-05-25T15:20:08.750Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01EhqHtinDvV1qffKtVyWmtT`</summary>

```json
{
  "pattern": "Ethics|ethics",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "02ae6990-6874-4e1a-b520-8dfb863e8acf",
  "isSidechain": false,
  "requestId": "req_011CbPWTm542NQi2JVvnE3Rq",
  "type": "assistant",
  "uuid": "b21087df-a000-4160-a5e2-8a8309869ce8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E7oNVRLoX6Qe3ur2fvaxDH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5042,
      "cache_read_input_tokens": 87899,
      "output_tokens": 8961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5042,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8961,
          "cache_read_input_tokens": 87899,
          "cache_creation_input_tokens": 5042,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5042
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

_source line 65 · 2026-05-25T15:20:08.763Z_

<details><summary>↩ Tool result · `toolu_01EhqHtinDvV1qffKtVyWmtT`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:15:Yes. The \textbf{Ethics Statement} (after Limitations) confirms no human subjects or private data are involved, all models are publicly available, and computational costs are reported.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:27:Yes. The Ethics Statement states that all evaluation environments (ScienceWorld, ALFWorld, MATH) are released under permissive open-source licenses (Apache 2.0 / MIT) and all models are publicly available for research use.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:48:Yes. Model sizes are specified (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Qwen2.5-72B-Instruct, Gemma-2-9B-it, Qwen3-0.6B/1.7B/4B). The Ethics Statement reports 2$\times$ NVIDIA RTX 5090 (32GB) and 4$\times$ NVIDIA RTX 6000 PRO (96GB), totaling approximately 200 GPU-hours with an estimated carbon footprint of approximately 25\,kg CO$_2$eq.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b21087df-a000-4160-a5e2-8a8309869ce8",
  "isSidechain": false,
  "promptId": "29552739-44ce-4e62-941f-84f8c7e13067",
  "type": "user",
  "uuid": "64c9ca47-ba12-4f36-ac3e-11566c542fed",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:15:Yes. The \\textbf{Ethics Statement} (after Limitations) confirms no human subjects or private data are involved, all models are publicly available, and computational costs are reported.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:27:Yes. The Ethics Statement states that all evaluation environments (ScienceWorld, ALFWorld, MATH) are released under permissive open-source licenses (Apache 2.0 / MIT) and all models are publicly available for research use.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:48:Yes. Model sizes are specified (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Qwen2.5-72B-Instruct, Gemma-2-9B-it, Qwen3-0.6B/1.7B/4B). The Ethics Statement reports 2$\\times$ NVIDIA RTX 5090 (32GB) and 4$\\times$ NVIDIA RTX 6000 PRO (96GB), totaling approximately 200 GPU-hours with an estimated carbon footprint of approximately 25\\,kg CO$_2$eq.",
    "numLines": 3
  },
  "sourceToolAssistantUUID": "b21087df-a000-4160-a5e2-8a8309869ce8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 66 · 2026-05-25T15:20:09.581Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01H34NZiw5mgpr9yLJ1PEJf7`</summary>

```json
{
  "pattern": "significantly",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true,
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "64c9ca47-ba12-4f36-ac3e-11566c542fed",
  "isSidechain": false,
  "requestId": "req_011CbPWTm542NQi2JVvnE3Rq",
  "type": "assistant",
  "uuid": "5d25ad4c-5573-4ec4-95d7-83411ec1109a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01E7oNVRLoX6Qe3ur2fvaxDH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5042,
      "cache_read_input_tokens": 87899,
      "output_tokens": 8961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5042,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8961,
          "cache_read_input_tokens": 87899,
          "cache_creation_input_tokens": 5042,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5042
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

_source line 67 · 2026-05-25T15:20:11.060Z_

```json
{
  "parentUuid": "6e378644-c4c7-41c6-ab8f-904a367b5295",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "58bdb057-439c-4266-8845-0e4c54e9ef8c",
  "timestamp": "2026-05-25T15:20:11.060Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 68_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 21 warnin…",
  "leafUuid": "58bdb057-439c-4266-8845-0e4c54e9ef8c",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Runtime record

_source line 69_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit for simgate-modular-routing",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Assistant

_source line 70 · 2026-05-25T15:21:16.619Z_

<details><summary>Logged reasoning block</summary>

```text
Good. Now let me compile all findings:

1. No Ethics Statement in main.tex, but the checklist references it 3 times.
2. No "significantly" used — good.
3. Abstract is ~137 words — under 200 limit.
4. Limitations section is the only one (no appendix limitations section) — good.

Let me also check for em-dashes more carefully in the main text content (not tables):

From the `---` search, in running text:
- abstract.tex:2 — multiple `---` in text


- introduction.tex:11, 15 — `---`  
- experiments.tex:65, 138 — text
- discussion.tex:9, 12, 13, 16 — text
- method.tex:41 — text

Table-cell `---` (acceptable): experiments.tex:85, 100; main.tex:183, 184, 348

Now I'm compiling the full audit. I should double-check the `---` instances more carefully since in LaTeX that's the standard way to typeset an em-dash, and the paper-writing norms have specific requirements about em-dash usage.

Looking through the grep results for `---` in running text, I'm finding roughly ten instances scattered across abstract, introduction, method, experiments, and discussion sections. I need to count these systematically to see how many are in actual prose versus tables.

Now checking Table 6 more carefully—the column header says "DAF (%)" but the caption describes it as "label fraction," which doesn't match the actual values shown. This looks like a labeling mismatch that needs clarification.

I should also examine whether the Discussion section is just restating numbers from the Results rather than providing new analysis.

Looking through the Discussion paragraphs, they're actually doing interpretive work—explaining *why* the router fails due to signal granularity mismatches, analyzing specific action patterns, and discussing practical implications and scope conditions. So that's not a problem.

But I've found something more serious: the NLP checklist references an "Ethics Statement" multiple times, but there's no actual Ethics Statement section in the main document. This means the checklist that gets submitted to OpenReview will claim content that doesn't exist.

Wait—I need to reconsider. The checklist is a template draft, not the actual submission form. The user fills in the real form on OpenReview directly, so this discrepancy is between the draft and the paper itself. Since an Ethics Statement is optional under the conference guidelines, the paper doesn't need one, but the checklist template shouldn't reference it. I should flag this as something the user needs to fix when completing the actual OpenReview form.

There's also a more critical issue: the checklist mentions "200 GPU-hours" and compute infrastructure details that only appear in the checklist file, not in the paper itself. If the conference requires compute information to be documented in the paper, this is a gap that needs addressing.

Now I'm checking the table references to make sure they're properly cited in the text. Table 6 is labeled correctly and referenced properly in the experiments section where it discusses the leave-one-task-out analysis.

One more thing to verify — the document uses the ACL review style package, which should be correct for EMNLP 2026 submissions going through ARR.

Now I'm noticing a framing inconsistency in the conclusion. It describes the router result as "inconclusive," but section 4.6 frames it as a "negative result" that actually supports the death-dominance finding. The section title itself says "Inconclusive Results," so the paper's using both framings — this seems intentional, though it could be clarified.

Let me also verify there are no SOTA claims, and check the abstract against the contributions. The abstract says boundary probes "confirm" the framework distinguishes routing mechanisms, but contribution (3) adds a qualifier about "full quantitative validation" being specific to ScienceWorld — that caveat isn't reflected in the abstract.

Looking at the introduction, it also uses "confirm" without hedging, so the claim strength varies between the narrative sections and the contribution list. This is a minor inconsistency worth flagging.

Now let me organize the issues I've found by severity.

There are no critical flaws that would lead to rejection. The narrative is solid overall.

For warnings that significantly impact quality: em-dashes appear throughout the text in ways that feel informal; Table 6's "DAF (%)" label is confusing since it shows label fractions rather than the score-based DAF metric mentioned elsewhere; the checklist references an Ethics Statement that doesn't exist in the paper; GPU type, hours, and CO2 emissions aren't reported in the main paper; and the abstract and introduction claim the boundary probes "confirm" findings without the qualification that full validation is specific to ScienceWorld.

For informational improvements: "Notably" appears once in the main text, which is worth noting.

The introduction is compressed into three paragraphs plus a contribution list rather than the standard five-paragraph structure, which works functionally but feels tight. The limitations section runs about 90 words across four points—acceptable for EMNLP 2026 standards but below the typical 150-word threshold. The claim about a 50-episode pilot being sufficient is validated retrospectively on the authors' own data, so prospective validation would strengthen it. There's also a minor framing inconsistency where the router results are called "inconclusive" in the section title and conclusion but described as "negative results consistent with death dominance" in the text itself. Finally, DAF is overloaded as a term—it refers both to a score-based metric (90.4%) and a label fraction (78.9%), yet the paper treats it as a single "primary, penalty-invariant diagnostic."

The Ethics Statement could be problematic if a reviewer checks the OpenReview form and finds a reference to something that doesn't exist there, though since the form is filled manually, the user should update it to match. Similarly, compute resources aren't explicitly in the paper itself—only agent inference parameters appear in the appendix—which might violate EMNLP's C1 checklist item about reporting computational budget and infrastructure. A reviewer reading just the PDF might miss this information if it's only in the form.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "58bdb057-439c-4266-8845-0e4c54e9ef8c",
  "isSidechain": false,
  "requestId": "req_011CbPWhrc5DWvqeqPVuFBaZ",
  "type": "assistant",
  "uuid": "5e7d0bd3-1920-4dca-86f1-23c54eadec96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T5RWUNi8CUqnRcRuHTLNcQ",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9862,
      "cache_read_input_tokens": 92941,
      "output_tokens": 4130,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9862,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4130,
          "cache_read_input_tokens": 92941,
          "cache_creation_input_tokens": 9862,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9862
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

_source line 71 · 2026-05-25T15:21:43.157Z_

审计完成，以下是结构化 findings。

```
[CONTENT_AUDIT_START]
- [warning] [叙事一致性] Table 6 (tab:loto-daf) 列标题为"DAF (%)"，但实际值为 death-label fraction（78.9%），而非 §3.4 定义的 score-based DAF（90.4%）。Caption 加了"(label fraction)"试图区分，但列标题和正文 DAF 定义冲突，审稿人易混淆两个 metric
- [warning] [叙事一致性] Abstract 和 Intro P3 均用"confirm"描述 MATH/ALFWorld boundary probes（"confirm the framework distinguishes"），但 Contribution (3) 加了关键限定语"while clarifying that full quantitative validation remains specific to ScienceWorld"。Abstract 的表述比 contribution list 更强，属 overclaim
- [warning] [符号] DAF 一词在全文中被 overload：§3.4 定义为 score-based metric (90.4%)，但 §4.1 同时将 label fraction (78.9%) 称为"primary, penalty-invariant diagnostic"。Table 6、§4.2 多处用"DAF"指代 label fraction。建议给 label fraction 一个独立名称（如"death-label fraction"），避免读者在两个含义间反复切换
- [warning] [去AI] LaTeX em-dash (---) 在正文多处出现，至少 10 处：abstract.tex:2 ("routing---deciding", "mechanisms---including")、introduction.tex:11 ("methods---whether inserting")、introduction.tex:15、method.tex:41、discussion.tex:12 ("points---an oracle degeneracy") 等。应替换为逗号、括号或拆句
- [warning] [可复现性] 计算资源信息（GPU 型号 RTX 5090/6000 PRO、200 GPU-hours、25 kg CO2eq）仅出现在 responsibleNLPchecklist.tex 中（用户自行填 OpenReview form），论文 PDF 正文和 appendix 均未报告。审稿人在论文中找不到 C1 要求的 compute budget 信息
- [warning] [贡献-范围对齐] responsibleNLPchecklist.tex 三处引用不存在的"Ethics Statement"（A2、B2、C1）。main.tex 中 Limitations 后直接接 bibliography，无 Ethics Statement section。用户填 OpenReview form 时需修正此不一致
- [info] [去AI] main.tex:651 (Appendix S) 使用 "Notably"，属 filler word
- [info] [章节结构] Introduction 为 3 段 + 贡献列表，省略了独立的"问题重要性"段。对于 diagnostic/analysis 论文可接受，但如果审稿人期待标准 5 段结构可能觉得 motivation 铺垫不足
- [info] [Claim强度] Contribution (2) 中"A ~50-episode pilot suffices for practitioners"仅基于对本文 4 个条件的 retrospective validation（Appendix R），非 prospective 验证。"suffices"措辞对 4/4 回溯样本偏强
- [info] [叙事一致性] §4.6 标题为"Router Training: Inconclusive Results"，但正文称其为"negative result...consistent with the death-dominance finding"，Conclusion 也用"inconclusive"。两种 framing 有张力：若结果与 death dominance 一致，更准确的说法是"negative result"而非"inconclusive"
- [info] [Limitations] Limitations 段约 90 words / 4 个限制点。符合 EMNLP 2026 用户规则（"一小段，3 个点左右"），但低于通用建议的 150-word 最低线。内容是实质性的，不回避核心弱点
- [info] [写作规则] Abstract 约 137 words（不含 footnote），远低于 200-word 上限 ✅
- [info] [写作规则] Limitations section 仅 1 个，在正文中，appendix 无 limitations section ✅
- [info] [审稿规则] 使用 \usepackage[review]{acl}，符合 ARR 投稿要求 ✅
[CONTENT_AUDIT_END]
```

**总结**：叙事主线一致性整体很强——Abstract/Intro/Method/Experiments/Conclusion 讲的是同一个故事（routing signal 被 death asymmetry 主导），无 A→B 漂移。主要问题集中在两方面：(1) DAF 术语 overloading（score-based 90.4% vs. label fraction 78.9% 混用同一名称），这会导致审稿人困惑；(2) em-dash 的 AI 风格痕迹需要清理。无 critical 级别问题。

[AUDIT_DONE]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5e7d0bd3-1920-4dca-86f1-23c54eadec96",
  "isSidechain": false,
  "requestId": "req_011CbPWhrc5DWvqeqPVuFBaZ",
  "type": "assistant",
  "uuid": "3f98f1b0-924c-40e3-96d4-990093b35dc9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T5RWUNi8CUqnRcRuHTLNcQ",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9862,
      "cache_read_input_tokens": 92941,
      "output_tokens": 4130,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9862,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4130,
          "cache_read_input_tokens": 92941,
          "cache_creation_input_tokens": 9862,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9862
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

_source line 72_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 21 warnin…",
  "leafUuid": "3f98f1b0-924c-40e3-96d4-990093b35dc9",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

### Runtime record

_source line 73_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit for simgate-modular-routing",
  "sessionId": "7a50ae44-8fc4-4ffa-9059-586963995fe2"
}
```

---

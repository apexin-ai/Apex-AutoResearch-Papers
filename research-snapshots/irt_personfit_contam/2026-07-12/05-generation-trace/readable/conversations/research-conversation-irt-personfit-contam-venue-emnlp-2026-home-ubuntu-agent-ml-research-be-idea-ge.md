# Research conversation: 项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_

**What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination? (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 83
- **Recorded user turns:** 1
- **Tool calls:** 25
- **Original source:** `logs/chats/exported-trajectories/account-2/e9a6f4dc-28b0-4890-b409-6b9949e65d46.jsonl`
- **Structured JSON:** [`e22878291f55a043ea0d.json`](../../sessions/e2/e22878291f55a043ea0d.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-24T12:16:48.510Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-24T12:16:48.510Z",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "content": "项目：irt_personfit_contam\nVenue：emnlp-2026\n论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper\n\nPhase 1 确定性检查结果：\n源码检查: passed=False, 1 critical, 1 warning\n一致性检查: 0 critical, 1 warning\n编译: ✅, 页数: 16\n内部信息: 0 critical, 0 warning\n\n━━━ 用户自定义规则（作为额外检查项）━━━\n## 用户自定义规则（必须遵守）\n### 写作规则\n\n- **[EMNLP 2026]** Limitations 章节只需要写一小段，覆盖 3 个点左右就可以了，不需要写得很长\n- **[EMNLP 2026]** ARR Responsible NLP Checklist在OpenReview的submission form里面（由用户手动填写），而不是在论文pdf里面\n- **[EMNLP 2026]** 一篇文章只能有一个limitations section，放在正文里面，appendix不能有 limitations section\n- **[EMNLP 2026]** abstract 不要超过 200 words\n\n### 审稿规则\n\n- **[EMNLP 2026]** “EMNLP 2026 通过 ARR 统一审稿，Main/Findings 不分开投稿（不是两个Track），Long/Short 也走同一审稿系统，Overall Assessment的评分标准如下：5 = Consider for Award（约前2.5%），4.5 = Borderline Award，4 = Conference（可被主会议接收），3.5 = Borderline Conference，3 = Findings（可被Findings接收），2.5 = Borderline Findings，2 = Resubmit next cycle（需大幅修改，可在下一周期完成），1.5 = Resubmit after next cycle（需大幅修改，无法在下一周期完成），1 = Do not resubmit（需完全重做或与*ACL无关）”\n- **[EMNLP 2026]** EMNLP 2026 restricts long paper submissions to a strict 8-page limit for main text, with unlimited space for references. Mandatory limitations and optional ethical considerations do not count towards this page limit, provided they do not contain excessive additional content.\n\n> 以上规则由用户配置，优先级等同于硬约束。违反会被 Reviewer 标记。\n请将以上规则逐条作为额外审计维度检查。违反的规则用 dimension `[写作规则]` 或 `[审稿规则]` 标记，severity 按实际影响判定。\n\n请按照你的角色指令执行内容结构审计。"
}
```

---

### Runtime record

_source line 2 · 2026-05-24T12:16:48.513Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-24T12:16:48.513Z",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

## Round 1

81 recorded events

### User

_source line 3 · 2026-05-24T12:16:48.545Z_

项目：irt_personfit_contam
Venue：emnlp-2026
论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper

Phase 1 确定性检查结果：
源码检查: passed=False, 1 critical, 1 warning
一致性检查: 0 critical, 1 warning
编译: ✅, 页数: 16
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
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "9f85eade-e06f-41e3-995b-861759006c86",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-24T12:16:48.544Z_

```json
{
  "parentUuid": "9f85eade-e06f-41e3-995b-861759006c86",
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
  "uuid": "3699da19-eb7f-4287-ad75-5e2db6f1e38f",
  "timestamp": "2026-05-24T12:16:48.544Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-24T12:16:48.544Z_

```json
{
  "parentUuid": "3699da19-eb7f-4287-ad75-5e2db6f1e38f",
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
  "uuid": "729312b2-527a-4572-a819-4b7b7c5e5dc5",
  "timestamp": "2026-05-24T12:16:48.544Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-24T12:16:48.544Z_

```json
{
  "parentUuid": "729312b2-527a-4572-a819-4b7b7c5e5dc5",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "e0e85629-21b3-4bea-9969-bae22479bde0",
  "timestamp": "2026-05-24T12:16:48.544Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
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
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Assistant

_source line 8 · 2026-05-24T12:17:01.632Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to perform a content structure audit on a paper. Let me start by reading the required skill files and the paper's .tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e0e85629-21b3-4bea-9969-bae22479bde0",
  "isSidechain": false,
  "requestId": "req_011CbMNuuHSigkeJeDhjwUSv",
  "type": "assistant",
  "uuid": "c8685157-15d2-4036-bbfe-4b742ff8b8e8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FRanTs8puhTfH22GqpiEDb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26618,
      "cache_read_input_tokens": 11846,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26618
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

_source line 9 · 2026-05-24T12:17:02.248Z_

开始执行内容结构审计。先加载审计标准和论文源码。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c8685157-15d2-4036-bbfe-4b742ff8b8e8",
  "isSidechain": false,
  "requestId": "req_011CbMNuuHSigkeJeDhjwUSv",
  "type": "assistant",
  "uuid": "a36bf8b7-aa7f-4c0f-9b98-4275bb81df99",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FRanTs8puhTfH22GqpiEDb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26618,
      "cache_read_input_tokens": 11846,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26618
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

_source line 10 · 2026-05-24T12:17:03.285Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UcZfxAWxHkErVdhrmgnnUc`</summary>

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
  "parentUuid": "a36bf8b7-aa7f-4c0f-9b98-4275bb81df99",
  "isSidechain": false,
  "requestId": "req_011CbMNuuHSigkeJeDhjwUSv",
  "type": "assistant",
  "uuid": "148b64e4-d3c6-4049-a628-cf0d815165b0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FRanTs8puhTfH22GqpiEDb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26618,
      "cache_read_input_tokens": 11846,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26618
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

_source line 11 · 2026-05-24T12:17:04.649Z_

<details><summary>↩ Tool result · `toolu_01DK5Mssv3GMS7ZMyZHpd9aC`</summary>

```text
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/background.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_empirical.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_simulation.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_setup.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/abstract.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/main.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_simulation.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_setup.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/background.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_empirical.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_ctrl_contam.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/discussion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/abstract.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/main.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/background.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/discussion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_simulation.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_setup.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_empirical.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_ctrl_contam.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/limitations.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/results.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/limitations.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/results.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "52294952-ea26-425d-ab27-e32c8126d9f6",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "b52f8943-d425-44b3-ac83-64d1c18277c8",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/experiments.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/background.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_empirical.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_simulation.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_setup.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/abstract.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_simulation.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_setup.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/background.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_empirical.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/method.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/sec_ctrl_contam.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/discussion.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/experiments.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/related_work.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/introduction.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/abstract.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/appendix.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/background.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/discussion.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/experiments.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_simulation.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_setup.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_empirical.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/method.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/sec_ctrl_contam.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/related_work.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/introduction.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/limitations.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/results.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/paper/sections/limitations.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/appendix.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex",
      "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/paper/sections/results.tex"
    ],
    "durationMs": 10,
    "numFiles": 48,
    "truncated": false
  },
  "sourceToolAssistantUUID": "52294952-ea26-425d-ab27-e32c8126d9f6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-24T12:17:03.298Z_

<details><summary>↩ Tool result · `toolu_01UcZfxAWxHkErVdhrmgnnUc`</summary>

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
  "parentUuid": "148b64e4-d3c6-4049-a628-cf0d815165b0",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "2a64c6af-f8f0-4c00-b7ba-cbf7084cb202",
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
  "sourceToolAssistantUUID": "148b64e4-d3c6-4049-a628-cf0d815165b0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 13 · 2026-05-24T12:17:04.401Z_

<details open><summary>🔧 Tool call — Read · `toolu_012pbZyPzARzLF9TZdiHi9gC`</summary>

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
  "parentUuid": "2a64c6af-f8f0-4c00-b7ba-cbf7084cb202",
  "isSidechain": false,
  "requestId": "req_011CbMNuuHSigkeJeDhjwUSv",
  "type": "assistant",
  "uuid": "059b47ac-f229-48e0-a2f3-045f359d05b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FRanTs8puhTfH22GqpiEDb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26618,
      "cache_read_input_tokens": 11846,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26618
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

_source line 14 · 2026-05-24T12:17:04.408Z_

<details><summary>↩ Tool result · `toolu_012pbZyPzARzLF9TZdiHi9gC`</summary>

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
  "parentUuid": "059b47ac-f229-48e0-a2f3-045f359d05b3",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "91f4805d-05d7-417b-b157-0845e5760dec",
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
  "sourceToolAssistantUUID": "059b47ac-f229-48e0-a2f3-045f359d05b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 15 · 2026-05-24T12:17:04.634Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01DK5Mssv3GMS7ZMyZHpd9aC`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "91f4805d-05d7-417b-b157-0845e5760dec",
  "isSidechain": false,
  "requestId": "req_011CbMNuuHSigkeJeDhjwUSv",
  "type": "assistant",
  "uuid": "52294952-ea26-425d-ab27-e32c8126d9f6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FRanTs8puhTfH22GqpiEDb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26618,
      "cache_read_input_tokens": 11846,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26618
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
  "lastPrompt": "项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper  Phase 1 确定性检查结果： 源码检查: passed=False, 1 critical, 1 warning 一致性检查:…",
  "leafUuid": "b52f8943-d425-44b3-ac83-64d1c18277c8",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Assistant

_source line 18 · 2026-05-24T12:17:09.715Z_

<details><summary>Logged reasoning block</summary>

```text
There are nested directories (paper/paper/paper, paper/paper, paper). I need to identify which is the actual paper being compiled. Let me check main.tex to see which one is the real one.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b52f8943-d425-44b3-ac83-64d1c18277c8",
  "isSidechain": false,
  "requestId": "req_011CbMNw6B4t7cvQFqwnXSmK",
  "type": "assistant",
  "uuid": "d5d92666-c9a8-4b77-8b25-f33b4c858ff4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GnooYrtYzBsPtwaiGVM668",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13650,
      "cache_read_input_tokens": 38464,
      "output_tokens": 177,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13650,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 177,
          "cache_read_input_tokens": 38464,
          "cache_creation_input_tokens": 13650,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13650
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

_source line 19 · 2026-05-24T12:17:10.690Z_

有三层嵌套目录。先确认哪个是实际编译的论文目录。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d5d92666-c9a8-4b77-8b25-f33b4c858ff4",
  "isSidechain": false,
  "requestId": "req_011CbMNw6B4t7cvQFqwnXSmK",
  "type": "assistant",
  "uuid": "8a432cce-cdfa-4cd8-bfc7-0584c2fdea96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GnooYrtYzBsPtwaiGVM668",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13650,
      "cache_read_input_tokens": 38464,
      "output_tokens": 177,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13650,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 177,
          "cache_read_input_tokens": 38464,
          "cache_creation_input_tokens": 13650,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13650
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

_source line 20 · 2026-05-24T12:17:11.198Z_

<details open><summary>🔧 Tool call — Read · `toolu_01A7UgY7KzgV3cGtVgzqfjE5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8a432cce-cdfa-4cd8-bfc7-0584c2fdea96",
  "isSidechain": false,
  "requestId": "req_011CbMNw6B4t7cvQFqwnXSmK",
  "type": "assistant",
  "uuid": "cea65b96-d515-4438-b9ef-1b1df419b87e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GnooYrtYzBsPtwaiGVM668",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13650,
      "cache_read_input_tokens": 38464,
      "output_tokens": 177,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13650,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 177,
          "cache_read_input_tokens": 38464,
          "cache_creation_input_tokens": 13650,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13650
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

_source line 21 · 2026-05-24T12:17:11.202Z_

<details><summary>↩ Tool result · `toolu_01A7UgY7KzgV3cGtVgzqfjE5`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	\usepackage{graphicx}
9	\usepackage{booktabs}
10	\usepackage{amsmath}
11	\usepackage{amssymb}
12	\usepackage{multirow}
13	\usepackage{xcolor}
14	\usepackage{subcaption}
15	\usepackage{enumitem}
16	
17	\newcommand{\irtfit}{\textsc{IRT-FIT}}
18	
19	\graphicspath{{../figures/paper/}}
20	
21	\title{What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\begin{abstract}
29	\input{sections/abstract}
30	\end{abstract}
31	
32	\input{sections/introduction}
33	\input{sections/related_work}
34	\input{sections/method}
35	\input{sections/results}
36	\input{sections/discussion}
37	\input{sections/conclusion}
38	
39	\input{sections/limitations}
40	
41	\section*{Reproducibility Statement}
42	Code and response data will be released upon acceptance.
43	Bootstrap confidence intervals use the percentile method with 10,000 resamples.
44	All three model families use clean baseline seeds 0--9 ($n{=}10$ per family).
45	Pre-calibrated 4PL item parameters are from the publicly available PSN-IRT item bank \citep{psnirt2026}.
46	Training used PyTorch 2.8.0, Transformers 5.8.1, PEFT 0.19.1, and BitsAndBytes 0.49.2.
47	Both benchmarks are publicly available under permissive licenses (MMLU: MIT; ARC-Challenge: CC-BY-SA).
48	
49	\bibliography{references}
50	
51	\appendix
52	\input{sections/appendix}
53	
54	\end{document}
55	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cea65b96-d515-4438-b9ef-1b1df419b87e",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "e36f93ec-2d67-430a-b78e-27f75d570b0d",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage{enumitem}\n\n\\newcommand{\\irtfit}{\\textsc{IRT-FIT}}\n\n\\graphicspath{{../figures/paper/}}\n\n\\title{What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\begin{abstract}\n\\input{sections/abstract}\n\\end{abstract}\n\n\\input{sections/introduction}\n\\input{sections/related_work}\n\\input{sections/method}\n\\input{sections/results}\n\\input{sections/discussion}\n\\input{sections/conclusion}\n\n\\input{sections/limitations}\n\n\\section*{Reproducibility Statement}\nCode and response data will be released upon acceptance.\nBootstrap confidence intervals use the percentile method with 10,000 resamples.\nAll three model families use clean baseline seeds 0--9 ($n{=}10$ per family).\nPre-calibrated 4PL item parameters are from the publicly available PSN-IRT item bank \\citep{psnirt2026}.\nTraining used PyTorch 2.8.0, Transformers 5.8.1, PEFT 0.19.1, and BitsAndBytes 0.49.2.\nBoth benchmarks are publicly available under permissive licenses (MMLU: MIT; ARC-Challenge: CC-BY-SA).\n\n\\bibliography{references}\n\n\\appendix\n\\input{sections/appendix}\n\n\\end{document}\n",
      "numLines": 55,
      "startLine": 1,
      "totalLines": 55
    }
  },
  "sourceToolAssistantUUID": "cea65b96-d515-4438-b9ef-1b1df419b87e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 22 · 2026-05-24T12:17:13.750Z_

<details><summary>Logged reasoning block</summary>

```text
The main paper is at `/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex`. It includes sections from `sections/` subdirectory. Let me read all the section files now.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e36f93ec-2d67-430a-b78e-27f75d570b0d",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "671dcb86-1137-4bb2-9a08-14409aa3dbc1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 23 · 2026-05-24T12:17:14.704Z_

确认了主编译目录为 `paper/`。现在并行读取所有 section 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "671dcb86-1137-4bb2-9a08-14409aa3dbc1",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "8ae6a048-5c93-4ead-9785-f61129f2bcfc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 24 · 2026-05-24T12:17:15.257Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FbAXaAx1MpaLa5AUxCoSzi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ae6a048-5c93-4ead-9785-f61129f2bcfc",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "c2156354-6f78-4a04-ab56-88f16cf2b561",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 25 · 2026-05-24T12:17:15.265Z_

<details><summary>↩ Tool result · `toolu_01FbAXaAx1MpaLa5AUxCoSzi`</summary>

```text
1	Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities.
2	We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination, requiring only binary response patterns and externally calibrated 4PL item parameters; diagnostic $\theta$-anchoring additionally requires a clean baseline.
3	A contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge.
4	Using $\ell_z^*$ in a matched-difference design ($\Delta\ell_z^*$) across three 7--8B model families ($n{=}10$ clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries:
5	(1) model-specific $\theta$-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; $\theta$-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4$\times$ amplification, inter-seed CV reduced from 60\% to 19\%);
6	(2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack $\ell_z^*$'s diagnostic capabilities (seen/unseen decomposition, mechanistic $\theta$-shift analysis);
7	and (3, exploratory) ability-dependent non-monotonic dose-response under free-$\theta$ estimation, driven by $\theta$-shift absorption; $\theta$-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels.
8	These findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c2156354-6f78-4a04-ab56-88f16cf2b561",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "9bd8da6d-d110-48f6-9073-cb01669ad27b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex",
      "content": "Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities.\nWe present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination, requiring only binary response patterns and externally calibrated 4PL item parameters; diagnostic $\\theta$-anchoring additionally requires a clean baseline.\nA contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge.\nUsing $\\ell_z^*$ in a matched-difference design ($\\Delta\\ell_z^*$) across three 7--8B model families ($n{=}10$ clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries:\n(1) model-specific $\\theta$-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; $\\theta$-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4$\\times$ amplification, inter-seed CV reduced from 60\\% to 19\\%);\n(2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack $\\ell_z^*$'s diagnostic capabilities (seen/unseen decomposition, mechanistic $\\theta$-shift analysis);\nand (3, exploratory) ability-dependent non-monotonic dose-response under free-$\\theta$ estimation, driven by $\\theta$-shift absorption; $\\theta$-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels.\nThese findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  },
  "sourceToolAssistantUUID": "c2156354-6f78-4a04-ab56-88f16cf2b561",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-24T12:17:16.221Z_

<details open><summary>🔧 Tool call — Read · `toolu_015Y2zVpDHVsqnm6wcpEu6sW`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9bd8da6d-d110-48f6-9073-cb01669ad27b",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "e08be099-2c91-4676-a1b8-6f738591a79c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 27 · 2026-05-24T12:17:16.229Z_

<details><summary>↩ Tool result · `toolu_015Y2zVpDHVsqnm6wcpEu6sW`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Benchmark contamination, the unintended inclusion of evaluation data in training corpora, poses a growing threat to the integrity of large language model (LLM) evaluation \citep{dodge2021, magar2022, sainz2023}.
4	As training corpora and public benchmarks both expand, the probability of overlap increases structurally \citep{jacovi2023, chang2024survey}.
5	When contamination occurs, benchmark scores no longer reflect genuine capability, undermining the primary mechanism by which the community compares and selects models.
6	
7	A range of detection methods have been proposed, but all require some form of privileged access beyond the binary response record.
8	N-gram overlap methods need the training corpus \citep{dodge2021, magar2022}.
9	Membership inference approaches require token-level probabilities \citep{minkprob2024, deng2024}.
10	Probing methods rely on crafted prompts \citep{golchin2024, oren2024}.
11	Performance-based methods require multiple test variants or output logits \citep{constat2024, codec2026}.
12	These methods form a detection frontier ordered by information access.
13	No existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.
14	
15	In this work, we focus on SFT-stage contamination---where benchmark answers are explicitly included in fine-tuning data---for three reasons.
16	First, controlled experiments require known ground-truth contamination sets, achievable through fine-tuning with specific benchmark items.
17	Second, SFT-stage contamination is increasingly relevant as fine-tuning-as-a-service platforms proliferate, creating new pathways for benchmark data to enter training mixtures.
18	Third, SFT provides a methodologically clean setting to characterize detection boundaries before extending to noisier pretraining scenarios.
19	
20	The need for detection from binary response patterns grows more pressing as models evolve.
21	\citet{wang2025fragility} show that all ten log-probability-based methods they evaluate perform at chance level on models trained with reinforcement learning (RL), because RL reshapes internal token distributions while preserving binary correctness patterns.
22	This motivates a fundamental question: \emph{what can binary response patterns reveal about contamination, and under what conditions?}
23	
24	We observe that a contaminated LLM is functionally analogous to a test-taker with item preknowledge: both produce response patterns in which difficult items are answered correctly through memorization rather than genuine ability.
25	This connection points to person-fit statistics, developed over four decades for cheating detection in educational testing \citep{drasgow1985, meijer2001, karabatsos2003, sinharay2017}.
26	The standardized statistic $\ell_z^*$ \citep{snijders2001} measures how well a response pattern conforms to Item Response Theory (IRT) model predictions.
27	Figure~\ref{fig:motivation} illustrates this analogy.
28	Despite the natural correspondence, no prior work has applied person-fit statistics to LLM benchmark contamination.
29	
30	\begin{figure}[t]
31	  \centering
32	  \includegraphics[width=\columnwidth]{fig_1_response_pattern.pdf}
33	  \caption{A clean model's responses track the IRT-predicted probability curve (left); a contaminated model shows anomalous successes on hard items (right, red diamonds), producing a large $|\Delta\ell_z^*|$ signal.}
34	  \label{fig:motivation}
35	\end{figure}
36	
37	Rather than proposing $\ell_z^*$ as a ready-to-deploy detection tool, we characterize the behavior boundaries of IRT person-fit statistics for LLM contamination detection.
38	Our framework operates at three layers: (i) pre-calibrated 4PL item parameters from the PSN-IRT item bank \citep{psnirt2026}, an external resource derived from 13,000+ models; (ii) binary response patterns obtained from the target model without access to weights or logits; and (iii) retrospective statistical inference requiring no model modification.
39	Using controlled contamination experiments across three 7--8B model families (Qwen2.5-7B, Llama-3.1-8B, Mistral-7B; $n{=}10$ clean seeds each) with PSN-IRT parameters, we identify three IRT-specific findings on MMLU \citep{hendrycks2021mmlu} and ARC-Challenge:
40	
41	\begin{enumerate}[leftmargin=*,nosep]
42	\item \textbf{Model-specific $\theta$-shift dynamics.} Contamination inflates ability estimates ($\hat{\theta}$), absorbing the person-fit signal; $\theta$-anchoring amplifies Qwen's multi-seed $|d|$ by 2.4$\times$ at 50\% contamination while reducing inter-seed CV from 60\% to 19\%, establishing $\theta$-anchoring as a necessary condition for reliable detection of high-ability models at high contamination. ARC-C reverses through a ceiling effect.
43	
44	\item \textbf{Detection-diagnosis tradeoff.} Simpler statistics yield stronger detection: accuracy $z$-scores produce $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics, and HT generally exceeds $\ell_z^*$. Yet the diagnostic power reverses: only $\ell_z^*$ supports seen/unseen decomposition, mechanistic $\theta$-shift analysis, and sensitivity to response-pattern structure (57/60 vs.\ 4/60 flagged cells on real-world data).
45	
46	\item \textbf{Non-monotonic dose-response under free-$\theta$ (exploratory).} Multi-seed Qwen trajectory ($|d|$: $4.15 \to 5.36 \to 7.44 \to 5.08$ at 5\%/15\%/25\%/50\%) shows attenuated non-monotonicity; $\theta$-anchoring eliminates the pattern and reveals strong positive dose-response ($|d|{=}12.32$ at 50\%). The non-monotonicity is a $\theta$-estimation artifact, not a detection boundary.
47	\end{enumerate}
48	
49	Our contributions are threefold:
50	(1) We provide the first empirical characterization of IRT person-fit behavior for LLM contamination, quantifying theoretically predicted phenomena ($\theta$-shift absorption, detection-diagnosis tradeoff) whose magnitudes and boundary conditions are not derivable from IRT theory alone.
51	(2) We establish that $\Delta\ell_z^*$ reliably detects SFT-stage contamination across three model families (all bootstrap 95\% CIs exclude zero, $n{=}10$).
52	(3) We document the detection-diagnosis tradeoff, clarifying what binary response patterns can and cannot reveal.
53	Findings~1--2 are confirmatory (pre-planned 15\%/50\% $\times$ 3 families); Finding~3 is exploratory (5\%/25\% added post-hoc).
54	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e08be099-2c91-4676-a1b8-6f738591a79c",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "0e48a06c-7e0d-4ab6-b682-389764d9a076",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex",
      "content": "\\section{Introduction}\\label{sec:introduction}\n\nBenchmark contamination, the unintended inclusion of evaluation data in training corpora, poses a growing threat to the integrity of large language model (LLM) evaluation \\citep{dodge2021, magar2022, sainz2023}.\nAs training corpora and public benchmarks both expand, the probability of overlap increases structurally \\citep{jacovi2023, chang2024survey}.\nWhen contamination occurs, benchmark scores no longer reflect genuine capability, undermining the primary mechanism by which the community compares and selects models.\n\nA range of detection methods have been proposed, but all require some form of privileged access beyond the binary response record.\nN-gram overlap methods need the training corpus \\citep{dodge2021, magar2022}.\nMembership inference approaches require token-level probabilities \\citep{minkprob2024, deng2024}.\nProbing methods rely on crafted prompts \\citep{golchin2024, oren2024}.\nPerformance-based methods require multiple test variants or output logits \\citep{constat2024, codec2026}.\nThese methods form a detection frontier ordered by information access.\nNo existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.\n\nIn this work, we focus on SFT-stage contamination---where benchmark answers are explicitly included in fine-tuning data---for three reasons.\nFirst, controlled experiments require known ground-truth contamination sets, achievable through fine-tuning with specific benchmark items.\nSecond, SFT-stage contamination is increasingly relevant as fine-tuning-as-a-service platforms proliferate, creating new pathways for benchmark data to enter training mixtures.\nThird, SFT provides a methodologically clean setting to characterize detection boundaries before extending to noisier pretraining scenarios.\n\nThe need for detection from binary response patterns grows more pressing as models evolve.\n\\citet{wang2025fragility} show that all ten log-probability-based methods they evaluate perform at chance level on models trained with reinforcement learning (RL), because RL reshapes internal token distributions while preserving binary correctness patterns.\nThis motivates a fundamental question: \\emph{what can binary response patterns reveal about contamination, and under what conditions?}\n\nWe observe that a contaminated LLM is functionally analogous to a test-taker with item preknowledge: both produce response patterns in which difficult items are answered correctly through memorization rather than genuine ability.\nThis connection points to person-fit statistics, developed over four decades for cheating detection in educational testing \\citep{drasgow1985, meijer2001, karabatsos2003, sinharay2017}.\nThe standardized statistic $\\ell_z^*$ \\citep{snijders2001} measures how well a response pattern conforms to Item Response Theory (IRT) model predictions.\nFigure~\\ref{fig:motivation} illustrates this analogy.\nDespite the natural correspondence, no prior work has applied person-fit statistics to LLM benchmark contamination.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_1_response_pattern.pdf}\n  \\caption{A clean model's responses track the IRT-predicted probability curve (left); a contaminated model shows anomalous successes on hard items (right, red diamonds), producing a large $|\\Delta\\ell_z^*|$ signal.}\n  \\label{fig:motivation}\n\\end{figure}\n\nRather than proposing $\\ell_z^*$ as a ready-to-deploy detection tool, we characterize the behavior boundaries of IRT person-fit statistics for LLM contamination detection.\nOur framework operates at three layers: (i) pre-calibrated 4PL item parameters from the PSN-IRT item bank \\citep{psnirt2026}, an external resource derived from 13,000+ models; (ii) binary response patterns obtained from the target model without access to weights or logits; and (iii) retrospective statistical inference requiring no model modification.\nUsing controlled contamination experiments across three 7--8B model families (Qwen2.5-7B, Llama-3.1-8B, Mistral-7B; $n{=}10$ clean seeds each) with PSN-IRT parameters, we identify three IRT-specific findings on MMLU \\citep{hendrycks2021mmlu} and ARC-Challenge:\n\n\\begin{enumerate}[leftmargin=*,nosep]\n\\item \\textbf{Model-specific $\\theta$-shift dynamics.} Contamination inflates ability estimates ($\\hat{\\theta}$), absorbing the person-fit signal; $\\theta$-anchoring amplifies Qwen's multi-seed $|d|$ by 2.4$\\times$ at 50\\% contamination while reducing inter-seed CV from 60\\% to 19\\%, establishing $\\theta$-anchoring as a necessary condition for reliable detection of high-ability models at high contamination. ARC-C reverses through a ceiling effect.\n\n\\item \\textbf{Detection-diagnosis tradeoff.} Simpler statistics yield stronger detection: accuracy $z$-scores produce $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics, and HT generally exceeds $\\ell_z^*$. Yet the diagnostic power reverses: only $\\ell_z^*$ supports seen/unseen decomposition, mechanistic $\\theta$-shift analysis, and sensitivity to response-pattern structure (57/60 vs.\\ 4/60 flagged cells on real-world data).\n\n\\item \\textbf{Non-monotonic dose-response under free-$\\theta$ (exploratory).} Multi-seed Qwen trajectory ($|d|$: $4.15 \\to 5.36 \\to 7.44 \\to 5.08$ at 5\\%/15\\%/25\\%/50\\%) shows attenuated non-monotonicity; $\\theta$-anchoring eliminates the pattern and reveals strong positive dose-response ($|d|{=}12.32$ at 50\\%). The non-monotonicity is a $\\theta$-estimation artifact, not a detection boundary.\n\\end{enumerate}\n\nOur contributions are threefold:\n(1) We provide the first empirical characterization of IRT person-fit behavior for LLM contamination, quantifying theoretically predicted phenomena ($\\theta$-shift absorption, detection-diagnosis tradeoff) whose magnitudes and boundary conditions are not derivable from IRT theory alone.\n(2) We establish that $\\Delta\\ell_z^*$ reliably detects SFT-stage contamination across three model families (all bootstrap 95\\% CIs exclude zero, $n{=}10$).\n(3) We document the detection-diagnosis tradeoff, clarifying what binary response patterns can and cannot reveal.\nFindings~1--2 are confirmatory (pre-planned 15\\%/50\\% $\\times$ 3 families); Finding~3 is exploratory (5\\%/25\\% added post-hoc).\n",
      "numLines": 54,
      "startLine": 1,
      "totalLines": 54
    }
  },
  "sourceToolAssistantUUID": "e08be099-2c91-4676-a1b8-6f738591a79c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-24T12:17:16.696Z_

<details open><summary>🔧 Tool call — Read · `toolu_01S3g96tYS4oMZyKkrbjzBt4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0e48a06c-7e0d-4ab6-b682-389764d9a076",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "49fa19c6-7628-477a-aca0-26f74c9b52b4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 29 · 2026-05-24T12:17:16.701Z_

<details><summary>↩ Tool result · `toolu_01S3g96tYS4oMZyKkrbjzBt4`</summary>

```text
1	\section{Related Work}\label{sec:related_work}
2	
3	\paragraph{Benchmark contamination detection.}
4	Contamination detection methods span a wide range of information requirements.
5	Corpus-search methods match benchmark items directly against pretraining data \citep{dodge2021, magar2022}, but require full corpus access unavailable for closed models.
6	Membership inference attacks (MIA) use token-level log-probabilities to distinguish training from unseen examples \citep{minkprob2024, deng2024}.
7	Generation-based probes elicit benchmark content via prompting \citep{golchin2024, golchin2024quiz, oren2024}.
8	Performance-based methods compare accuracy on target and reference sets \citep{constat2024, pacost2024, codec2026}, requiring multiple evaluations or in-context learning passes.
9	\citet{zhou2023benchmark} and \citet{sainz2023} argue for systematic contamination measurement, \citet{jacovi2023} propose mitigation strategies, and \citet{bordt2025forget} show that contamination can be ``forgotten'' under sufficient continued training.
10	\citet{han2026quantifying} quantify contamination in psychometric evaluations of LLMs, demonstrating that memorization effects extend beyond standard benchmarks.
11	\citet{kattamuri2025radar} take a mechanistic interpretability approach, using activation patterns to distinguish recall-based from reasoning-based responses; our work instead operates purely on behavioral response patterns without access to model internals.
12	\citet{fu2025contamination} systematically evaluate detection method assumptions, finding that most methods degrade under realistic conditions; our work contributes a psychometric perspective to this ongoing evaluation.
13	
14	A critical limitation unites all token-level methods: \citet{wang2025fragility} show that RL post-training renders MIA-based detectors no better than random across 10 methods and 4 benchmarks, because RL reshapes token distributions while largely preserving binary correctness patterns.
15	\citet{selfcritique2026} and \citet{zhang2026rlvr} propose RL-specific solutions but require generation-level access.
16	Our approach requires no access to model weights, logits, or training data---only binary response patterns and externally calibrated item parameters from PSN-IRT \citep{psnirt2026}.
17	
18	\paragraph{IRT for LLM evaluation.}
19	Item Response Theory has seen growing adoption in NLP and ML evaluation.
20	\citet{martinezplumed2019} applied IRT to analyze machine learning classifiers at the instance level, establishing that item difficulty and discrimination parameters capture meaningful variation across models.
21	\citet{lalor2019} proposed estimating IRT parameters from DNN-generated response patterns, removing the need for human annotators.
22	\citet{rodriguez2021} demonstrated that IRT-informed item weighting improves leaderboard rankings over raw accuracy.
23	\citet{polo2024tinybenchmarks} used IRT-based item selection to reduce benchmark sizes by 100$\times$ while preserving model rankings, and \citet{atlas2025} developed adaptive testing procedures for efficient LLM evaluation.
24	Most directly relevant, \citet{psnirt2026} calibrated 4PL item parameters for over 13,000 models across 11 benchmarks, providing the item bank our framework builds on.
25	All of these works use IRT for ability estimation or benchmark efficiency; none apply \emph{person-fit} statistics for contamination detection.
26	
27	\paragraph{Person-fit statistics in psychometrics.}
28	Person-fit analysis has a long history in educational measurement for detecting aberrant test-taking behavior \citep[see][for a textbook treatment]{embretson2000}.
29	\citet{levine1988} formalized optimal appropriateness measurement; \citet{drasgow1985} introduced $\ell_z$, a standardized log-likelihood residual; \citet{snijders2001} derived the corrected $\ell_z^*$ that accounts for ability estimation uncertainty.
30	\citet{karabatsos2003} compared 36 person-fit statistics and found $\ell_z$ among the most powerful for detecting cheating; \citet{sinharay2017personfit} revisited these simulations and confirmed comparable power between parametric and nonparametric statistics.
31	We select $\ell_z^*$ for its theoretical grounding and HT \citep{vanderflier1982} as a nonparametric complement, following their top-ranked performance in that comparison.
32	\citet{reise1990} and \citet{meijer2001} provide systematic evaluations of person-fit methodology.
33	\citet{sinharay2017} showed that $\ell_z^*$ is particularly effective when the set of compromised items is known, a setting analogous to benchmark contamination where memorized items constitute the compromised set.
34	Our work transfers this psychometric toolkit to LLM evaluation, treating each model as an examinee whose item-level response pattern may reveal memorization.
35	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "49fa19c6-7628-477a-aca0-26f74c9b52b4",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "b7aeea19-cb62-4e1e-9be6-dbe37fb20056",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex",
      "content": "\\section{Related Work}\\label{sec:related_work}\n\n\\paragraph{Benchmark contamination detection.}\nContamination detection methods span a wide range of information requirements.\nCorpus-search methods match benchmark items directly against pretraining data \\citep{dodge2021, magar2022}, but require full corpus access unavailable for closed models.\nMembership inference attacks (MIA) use token-level log-probabilities to distinguish training from unseen examples \\citep{minkprob2024, deng2024}.\nGeneration-based probes elicit benchmark content via prompting \\citep{golchin2024, golchin2024quiz, oren2024}.\nPerformance-based methods compare accuracy on target and reference sets \\citep{constat2024, pacost2024, codec2026}, requiring multiple evaluations or in-context learning passes.\n\\citet{zhou2023benchmark} and \\citet{sainz2023} argue for systematic contamination measurement, \\citet{jacovi2023} propose mitigation strategies, and \\citet{bordt2025forget} show that contamination can be ``forgotten'' under sufficient continued training.\n\\citet{han2026quantifying} quantify contamination in psychometric evaluations of LLMs, demonstrating that memorization effects extend beyond standard benchmarks.\n\\citet{kattamuri2025radar} take a mechanistic interpretability approach, using activation patterns to distinguish recall-based from reasoning-based responses; our work instead operates purely on behavioral response patterns without access to model internals.\n\\citet{fu2025contamination} systematically evaluate detection method assumptions, finding that most methods degrade under realistic conditions; our work contributes a psychometric perspective to this ongoing evaluation.\n\nA critical limitation unites all token-level methods: \\citet{wang2025fragility} show that RL post-training renders MIA-based detectors no better than random across 10 methods and 4 benchmarks, because RL reshapes token distributions while largely preserving binary correctness patterns.\n\\citet{selfcritique2026} and \\citet{zhang2026rlvr} propose RL-specific solutions but require generation-level access.\nOur approach requires no access to model weights, logits, or training data---only binary response patterns and externally calibrated item parameters from PSN-IRT \\citep{psnirt2026}.\n\n\\paragraph{IRT for LLM evaluation.}\nItem Response Theory has seen growing adoption in NLP and ML evaluation.\n\\citet{martinezplumed2019} applied IRT to analyze machine learning classifiers at the instance level, establishing that item difficulty and discrimination parameters capture meaningful variation across models.\n\\citet{lalor2019} proposed estimating IRT parameters from DNN-generated response patterns, removing the need for human annotators.\n\\citet{rodriguez2021} demonstrated that IRT-informed item weighting improves leaderboard rankings over raw accuracy.\n\\citet{polo2024tinybenchmarks} used IRT-based item selection to reduce benchmark sizes by 100$\\times$ while preserving model rankings, and \\citet{atlas2025} developed adaptive testing procedures for efficient LLM evaluation.\nMost directly relevant, \\citet{psnirt2026} calibrated 4PL item parameters for over 13,000 models across 11 benchmarks, providing the item bank our framework builds on.\nAll of these works use IRT for ability estimation or benchmark efficiency; none apply \\emph{person-fit} statistics for contamination detection.\n\n\\paragraph{Person-fit statistics in psychometrics.}\nPerson-fit analysis has a long history in educational measurement for detecting aberrant test-taking behavior \\citep[see][for a textbook treatment]{embretson2000}.\n\\citet{levine1988} formalized optimal appropriateness measurement; \\citet{drasgow1985} introduced $\\ell_z$, a standardized log-likelihood residual; \\citet{snijders2001} derived the corrected $\\ell_z^*$ that accounts for ability estimation uncertainty.\n\\citet{karabatsos2003} compared 36 person-fit statistics and found $\\ell_z$ among the most powerful for detecting cheating; \\citet{sinharay2017personfit} revisited these simulations and confirmed comparable power between parametric and nonparametric statistics.\nWe select $\\ell_z^*$ for its theoretical grounding and HT \\citep{vanderflier1982} as a nonparametric complement, following their top-ranked performance in that comparison.\n\\citet{reise1990} and \\citet{meijer2001} provide systematic evaluations of person-fit methodology.\n\\citet{sinharay2017} showed that $\\ell_z^*$ is particularly effective when the set of compromised items is known, a setting analogous to benchmark contamination where memorized items constitute the compromised set.\nOur work transfers this psychometric toolkit to LLM evaluation, treating each model as an examinee whose item-level response pattern may reveal memorization.\n",
      "numLines": 35,
      "startLine": 1,
      "totalLines": 35
    }
  },
  "sourceToolAssistantUUID": "49fa19c6-7628-477a-aca0-26f74c9b52b4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-24T12:17:17.163Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HrUnZnyPsqECsafBLgx9n9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b7aeea19-cb62-4e1e-9be6-dbe37fb20056",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "0d22af11-3ceb-49ea-b04a-bda1194ef307",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 31 · 2026-05-24T12:17:17.168Z_

<details><summary>↩ Tool result · `toolu_01HrUnZnyPsqECsafBLgx9n9`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{IRT Person-Fit Framework}
5	\label{sec:framework}
6	
7	We adopt the four-parameter logistic (4PL) IRT model to characterize contamination-induced aberrance in LLM response patterns.
8	The 4PL model defines the probability that a model with ability $\theta$ answers item $i$ correctly:
9	\begin{equation}
10	  P_i(\theta) = c_i + (d_i - c_i)\,\frac{1}{1 + e^{-a_i(\theta - b_i)}}
11	  \label{eq:4pl}
12	\end{equation}
13	where $a_i$ is discrimination, $b_i$ difficulty, $c_i$ the lower asymptote (guessing), and $d_i$ the upper asymptote (slip).
14	Item parameters are pre-calibrated by PSN-IRT \citep{psnirt2026} from a large-scale leaderboard dataset; we use these external parameters rather than re-estimating from potentially contaminated data, since our MML-EM refit shows discrimination recovery degrades to $r_a{=}0.127$ on contaminated leaderboard data.
15	
16	Given item parameters and a binary response vector $\mathbf{x} = (x_1, \ldots, x_n)$, we compute the person-fit statistic $\ell_z^*$ \citep{snijders2001}, a standardized log-likelihood residual quantifying deviation between observed and expected response patterns.
17	The Snijders correction accounts for estimation uncertainty in $\hat{\theta}_{\text{MLE}}$, so that $\ell_z^* \sim \mathcal{N}(0,1)$ under the null \citep{drasgow1985, snijders2001}; \citet{magis2012} provide a detailed treatment of how response model selection and ability estimation affect $\ell_z^*$.
18	Large negative $\ell_z^*$ indicates aberrant responding (unexpected failures on easy items or unexpected successes on hard items); large positive values indicate over-consistent patterns.
19	
20	\subsection{$\Delta\ell_z^*$ Matched-Difference Design}
21	\label{sec:did}
22	
23	LLM response patterns systematically violate IRT assumptions of local independence and unidimensionality.
24	In our empirical data, 57 of 60 model-benchmark cells yield $|\ell_z^*| > 1.96$ even absent contamination, rendering absolute thresholds uninformative.
25	We address this through a matched-difference design.
26	
27	For controlled experiments with clean baselines, we compute:
28	\begin{equation}
29	  \Delta\ell_z^* = \ell_{z,\text{contam}}^{*} - \bar{\ell}_{z,\text{clean}}^{*}
30	  \label{eq:delta_lz}
31	\end{equation}
32	where $\bar{\ell}_{z,\text{clean}}^{*}$ averages over $n{=}10$ clean seeds.
33	The shared model misfit cancels, isolating contamination-specific aberrance.
34	We quantify effect sizes as $d = (\ell_{z,\text{contam}}^{*} - \bar{\ell}_{z,\text{clean}}^{*})\,/\,s_{\text{clean}}$, where $s_{\text{clean}}$ is the SD of the $n{=}10$ clean-seed $\ell_z^*$ values; with a single contaminated observation per condition, $d$ is a standardized departure rather than a two-sample effect size (Hedges' $g = J \cdot d$, $J \approx 0.914$ for $n{=}10$; \citealp{hedges1981}).
35	We report percentile bootstrap 95\% CIs (10,000 resamples) reflecting clean-seed variability only; BCa correction (Appendix~\ref{app:bca}) generally confirms conservative coverage; multi-seed contamination-run variance appears in Appendix~\ref{app:reproducibility}.
36	
37	For deployment without clean baselines, cross-benchmark comparison provides the reference: the target benchmark's $\ell_z^*$ is compared against benchmarks presumed clean from the same model.
38	Significance thresholds derive from a nonparametric bootstrap null rather than the asymptotic $\mathcal{N}(0,1)$ reference, accommodating residual model misspecification.
39	Simulation analysis (Appendix~\ref{app:local_dep}) confirms that the matched-difference design is robust to local dependence at realistic levels ($d_{\text{ratio}} \geq 0.93$ for $\sigma_\tau \leq 0.5$) and maintains ${\geq}98.5\%$ power even under contamination-specific asymmetric dependence.
40	
41	\subsection{Experimental Setup}
42	\label{sec:setup}
43	
44	\paragraph{Models and contamination.}
45	We validate on three 7--8B model families: Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, and Mistral-7B-Instruct-v0.3.
46	Each is fine-tuned with QLoRA (rank\,$=$\,16, $\alpha$\,$=$\,32; full hyperparameters in Appendix~\ref{app:hyperparams}) under clean and contaminated conditions at varying levels: at $X\%$ contamination, $X\%$ of SFT training examples are benchmark items (questions paired with gold answers in the standard evaluation format), with the remainder drawn from a general instruction-following dataset.
47	All three families are tested at 15\% and 50\% contamination.
48	Following initial observation of non-monotonic dose-response for Qwen, we added 5\% and 25\% conditions for Qwen to trace the full dose-response curve.
49	Contamination subsets are nested (5\% $\subset$ 15\% $\subset$ 25\% $\subset$ 50\%) using a fixed item-selection seed; a robustness check with an alternative seed confirms consistent $\ell_z^*$ values (Appendix~\ref{app:reproducibility}).
50	The 25\% condition was subsequently extended to Llama to test whether the pattern generalizes; Mistral was not tested at 5\% or 25\% due to computational constraints.
51	We train $n{=}10$ independent clean seeds per model to establish baseline variability and construct bootstrap confidence intervals.
52	Reported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\%/25\%/50\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\ref{app:reproducibility}).
53	
54	\paragraph{Benchmarks.}
55	We evaluate on MMLU \citep{hendrycks2021mmlu} (14,042 items) and ARC-Challenge \citep{clark2018arc} (295 items), spanning two orders of magnitude in benchmark size.
56	All 4PL item parameters are from \citet{psnirt2026}.
57	ARC-Challenge experiments were conducted on Qwen only, as the primary evaluation of cross-benchmark generalizability; extending to additional families was constrained by computational budget.
58	
59	\paragraph{Post-RL extension.}
60	To probe behavior boundaries beyond SFT, we apply Group Relative Policy Optimization (GRPO; \citealp{shao2024}) to one contaminated Qwen model (15\% MMLU) for 1,500 steps, evaluating at three checkpoints.
61	This extension is $N{=}1$ (single model family, single contamination level).
62	
63	\paragraph{Contamination model.}
64	QLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.
65	We refer to the contaminated benchmark items as \emph{seen items} and the remaining benchmark items not included in training as \emph{unseen items}; this partition enables decomposition of person-fit statistics to assess whether the contamination signal concentrates on memorized items (\S\ref{sec:degradation}).
66	Our findings are scoped to SFT-based contamination and may not generalize to pretraining contamination, which operates through different learning dynamics.
67	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0d22af11-3ceb-49ea-b04a-bda1194ef307",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "60a6ebda-7dfd-451d-a815-e856e0901186",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{IRT Person-Fit Framework}\n\\label{sec:framework}\n\nWe adopt the four-parameter logistic (4PL) IRT model to characterize contamination-induced aberrance in LLM response patterns.\nThe 4PL model defines the probability that a model with ability $\\theta$ answers item $i$ correctly:\n\\begin{equation}\n  P_i(\\theta) = c_i + (d_i - c_i)\\,\\frac{1}{1 + e^{-a_i(\\theta - b_i)}}\n  \\label{eq:4pl}\n\\end{equation}\nwhere $a_i$ is discrimination, $b_i$ difficulty, $c_i$ the lower asymptote (guessing), and $d_i$ the upper asymptote (slip).\nItem parameters are pre-calibrated by PSN-IRT \\citep{psnirt2026} from a large-scale leaderboard dataset; we use these external parameters rather than re-estimating from potentially contaminated data, since our MML-EM refit shows discrimination recovery degrades to $r_a{=}0.127$ on contaminated leaderboard data.\n\nGiven item parameters and a binary response vector $\\mathbf{x} = (x_1, \\ldots, x_n)$, we compute the person-fit statistic $\\ell_z^*$ \\citep{snijders2001}, a standardized log-likelihood residual quantifying deviation between observed and expected response patterns.\nThe Snijders correction accounts for estimation uncertainty in $\\hat{\\theta}_{\\text{MLE}}$, so that $\\ell_z^* \\sim \\mathcal{N}(0,1)$ under the null \\citep{drasgow1985, snijders2001}; \\citet{magis2012} provide a detailed treatment of how response model selection and ability estimation affect $\\ell_z^*$.\nLarge negative $\\ell_z^*$ indicates aberrant responding (unexpected failures on easy items or unexpected successes on hard items); large positive values indicate over-consistent patterns.\n\n\\subsection{$\\Delta\\ell_z^*$ Matched-Difference Design}\n\\label{sec:did}\n\nLLM response patterns systematically violate IRT assumptions of local independence and unidimensionality.\nIn our empirical data, 57 of 60 model-benchmark cells yield $|\\ell_z^*| > 1.96$ even absent contamination, rendering absolute thresholds uninformative.\nWe address this through a matched-difference design.\n\nFor controlled experiments with clean baselines, we compute:\n\\begin{equation}\n  \\Delta\\ell_z^* = \\ell_{z,\\text{contam}}^{*} - \\bar{\\ell}_{z,\\text{clean}}^{*}\n  \\label{eq:delta_lz}\n\\end{equation}\nwhere $\\bar{\\ell}_{z,\\text{clean}}^{*}$ averages over $n{=}10$ clean seeds.\nThe shared model misfit cancels, isolating contamination-specific aberrance.\nWe quantify effect sizes as $d = (\\ell_{z,\\text{contam}}^{*} - \\bar{\\ell}_{z,\\text{clean}}^{*})\\,/\\,s_{\\text{clean}}$, where $s_{\\text{clean}}$ is the SD of the $n{=}10$ clean-seed $\\ell_z^*$ values; with a single contaminated observation per condition, $d$ is a standardized departure rather than a two-sample effect size (Hedges' $g = J \\cdot d$, $J \\approx 0.914$ for $n{=}10$; \\citealp{hedges1981}).\nWe report percentile bootstrap 95\\% CIs (10,000 resamples) reflecting clean-seed variability only; BCa correction (Appendix~\\ref{app:bca}) generally confirms conservative coverage; multi-seed contamination-run variance appears in Appendix~\\ref{app:reproducibility}.\n\nFor deployment without clean baselines, cross-benchmark comparison provides the reference: the target benchmark's $\\ell_z^*$ is compared against benchmarks presumed clean from the same model.\nSignificance thresholds derive from a nonparametric bootstrap null rather than the asymptotic $\\mathcal{N}(0,1)$ reference, accommodating residual model misspecification.\nSimulation analysis (Appendix~\\ref{app:local_dep}) confirms that the matched-difference design is robust to local dependence at realistic levels ($d_{\\text{ratio}} \\geq 0.93$ for $\\sigma_\\tau \\leq 0.5$) and maintains ${\\geq}98.5\\%$ power even under contamination-specific asymmetric dependence.\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\n\\paragraph{Models and contamination.}\nWe validate on three 7--8B model families: Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, and Mistral-7B-Instruct-v0.3.\nEach is fine-tuned with QLoRA (rank\\,$=$\\,16, $\\alpha$\\,$=$\\,32; full hyperparameters in Appendix~\\ref{app:hyperparams}) under clean and contaminated conditions at varying levels: at $X\\%$ contamination, $X\\%$ of SFT training examples are benchmark items (questions paired with gold answers in the standard evaluation format), with the remainder drawn from a general instruction-following dataset.\nAll three families are tested at 15\\% and 50\\% contamination.\nFollowing initial observation of non-monotonic dose-response for Qwen, we added 5\\% and 25\\% conditions for Qwen to trace the full dose-response curve.\nContamination subsets are nested (5\\% $\\subset$ 15\\% $\\subset$ 25\\% $\\subset$ 50\\%) using a fixed item-selection seed; a robustness check with an alternative seed confirms consistent $\\ell_z^*$ values (Appendix~\\ref{app:reproducibility}).\nThe 25\\% condition was subsequently extended to Llama to test whether the pattern generalizes; Mistral was not tested at 5\\% or 25\\% due to computational constraints.\nWe train $n{=}10$ independent clean seeds per model to establish baseline variability and construct bootstrap confidence intervals.\nReported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\\%/25\\%/50\\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\\ref{app:reproducibility}).\n\n\\paragraph{Benchmarks.}\nWe evaluate on MMLU \\citep{hendrycks2021mmlu} (14,042 items) and ARC-Challenge \\citep{clark2018arc} (295 items), spanning two orders of magnitude in benchmark size.\nAll 4PL item parameters are from \\citet{psnirt2026}.\nARC-Challenge experiments were conducted on Qwen only, as the primary evaluation of cross-benchmark generalizability; extending to additional families was constrained by computational budget.\n\n\\paragraph{Post-RL extension.}\nTo probe behavior boundaries beyond SFT, we apply Group Relative Policy Optimization (GRPO; \\citealp{shao2024}) to one contaminated Qwen model (15\\% MMLU) for 1,500 steps, evaluating at three checkpoints.\nThis extension is $N{=}1$ (single model family, single contamination level).\n\n\\paragraph{Contamination model.}\nQLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.\nWe refer to the contaminated benchmark items as \\emph{seen items} and the remaining benchmark items not included in training as \\emph{unseen items}; this partition enables decomposition of person-fit statistics to assess whether the contamination signal concentrates on memorized items (\\S\\ref{sec:degradation}).\nOur findings are scoped to SFT-based contamination and may not generalize to pretraining contamination, which operates through different learning dynamics.\n",
      "numLines": 67,
      "startLine": 1,
      "totalLines": 67
    }
  },
  "sourceToolAssistantUUID": "0d22af11-3ceb-49ea-b04a-bda1194ef307",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-24T12:17:17.638Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KsgRVxXWoxz3xxpLusZX4J`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "60a6ebda-7dfd-451d-a815-e856e0901186",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "b6bd479c-e236-487d-bc4f-8c1ddc1410e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 33 · 2026-05-24T12:17:17.642Z_

<details><summary>↩ Tool result · `toolu_01KsgRVxXWoxz3xxpLusZX4J`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	\subsection{Detection Signal Across Model Families}
5	\label{sec:detection}
6	
7	Table~\ref{tab:cohens_d} presents Cohen's $d$ effect sizes for $\ell_z^*$ across three model families and two benchmarks.
8	All confidence intervals exclude zero, confirming that $\Delta\ell_z^*$ reliably separates contaminated from clean models at both contamination levels.
9	
10	On MMLU, effect sizes range from $|d|{=}2.30$ (Llama at 50\%) to $|d|{=}7.44$ (Qwen at 25\%), with Qwen at 5\% ($|d|{=}4.15$) confirming detection at the lowest contamination level tested. Llama ($|d|{=}2.80$/$2.56$/$2.30$) and Mistral ($|d|{=}3.37$/$4.09$) show comparable magnitudes.
11	On ARC-C (295 items), Qwen yields $|d|{=}3.16$ at 15\% and $|d|{=}5.30$ at 50\%, demonstrating that detection remains feasible even on small benchmarks when contamination is sufficiently concentrated.
12	
13	Clean-model $\ell_z^*$ baselines diverge substantially across families: Qwen ${+}8.68$ ($\text{SD}{=}0.74$), Mistral ${+}4.02$ ($\text{SD}{=}2.05$), Llama ${+}0.26$ ($\text{SD}{=}1.54$), and ARC-C Qwen ${-}5.42$ ($\text{SD}{=}0.16$); this divergence reflects difficulty-ordering consistency rather than accuracy level (Appendix~\ref{app:baseline_meaning}).
14	Absolute $\ell_z^*$ thresholds would produce contradictory results: Qwen's contaminated $\ell_z^*$ at 15\% (${+}3.8$) is still positive.
15	The $\Delta\ell_z^*$ design normalizes these divergent baselines: Cohen's $d$ yields comparable effect sizes ($|d|{=}2.30$--$7.44$) despite order-of-magnitude differences.
16	Figure~\ref{fig:heatmap} provides a visual summary.
17	
18	\begin{table}[t]
19	\centering
20	\caption{Cohen's $d$ for $\Delta\ell_z^*$ across model families ($n{=}10$ clean seeds). Single-seed conditions: percentile bootstrap 95\% CI (10,000 resamples). $^{\dagger}$Multi-seed conditions: mean $\pm$ SD ($n{=}3$ independent runs). All CIs exclude zero.}
21	\label{tab:cohens_d}
22	\footnotesize
23	\resizebox{\columnwidth}{!}{%
24	\begin{tabular}{@{}llrrrr@{}}
25	\toprule
26	Model & Bench. & $d$ (5\%) [CI] & $d$ (15\%) [CI] & $d$ (25\%) [CI] & $d$ (50\%) [CI] \\
27	\midrule
28	Qwen$^{\dagger}$ & MMLU & $-4.15$ [$-9.9$, $-2.7$] & $-5.36$ ($\pm$1.10) & $-7.44$ ($\pm$1.86) & $-5.08$ ($\pm$3.02) \\
29	Llama$^{\dagger}$ & MMLU & --- & $-2.80$ ($\pm$0.60) & $-2.56$ ($\pm$0.52) & $-2.30$ ($\pm$0.30) \\
30	Mistral$^{\dagger}$ & MMLU & --- & $-3.37$ ($\pm$0.68) & --- & $-4.09$ ($\pm$0.53) \\
31	Qwen$^{\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\
32	\bottomrule
33	\multicolumn{6}{@{}l}{\scriptsize $^{\dagger}$Multi-seed conditions: means ($n{=}3$ independent runs) shown as $\pm$SD; remaining conditions are single-seed with bootstrap CIs. Per-seed values in Appendix~\ref{app:reproducibility}.}
34	\end{tabular}}
35	\end{table}
36	
37	\begin{figure*}[t]
38	  \centering
39	  \includegraphics[width=\textwidth]{fig_heatmap.pdf}
40	  \caption{Cohen's $|d|$ heatmap (values from Table~\ref{tab:cohens_d}; multi-seed means where available). Blue intensity reflects effect-size magnitude. Grey cells: conditions not tested.}
41	  \label{fig:heatmap}
42	\end{figure*}
43	
44	\subsection{Model-Specific $\theta$-Shift Dynamics}
45	\label{sec:theta_dynamics}
46	
47	The cross-family variation in Table~\ref{tab:cohens_d}---Qwen's $|d|$ declining from 25\% to 50\% while Llama's remains flat---suggests detection sensitivity depends on more than contamination dose.
48	Contamination raises overall accuracy, which inflates $\hat{\theta}_{\text{MLE}}$; a higher $\hat{\theta}$ ``explains away'' anomalous successes on hard items, absorbing the contamination signal into the ability estimate.
49	We term this \emph{$\theta$-shift absorption}.
50	The magnitude of $\theta$-shift is comparable across families---Qwen ($\Delta\theta{=}0.47$ at 50\%) and Llama ($\Delta\theta{=}0.52$)---yet their fixed-$\theta$ amplification diverges markedly (Table~\ref{tab:theta_fixed}), indicating that $\theta$-shift magnitude alone does not predict fixed-$\theta$ benefit.
51	Figure~\ref{fig:theta_scatter} plots baseline accuracy against Cohen's $|d|$ for all model-benchmark combinations.
52	
53	$\theta$-shift absorption is the dominant source of detection variability for high-ability models at high contamination:
54	(i) fixed-$\theta$ estimation amplifies Qwen's multi-seed $|d|$ by 2.4$\times$ at 50\% ($5.08 \to 12.32$; Table~\ref{tab:theta_fixed}), while Llama shows no amplification ($0.4\times$);
55	(ii) $\theta$-anchoring reduces Qwen's inter-seed CV from 60\% to 19\%, confirming that training-run variance is driven by $\theta$-shift stochasticity rather than true signal variance;
56	(iii) the cross-model ranking under free-$\theta$ is seed-dependent at 50\%, making $\theta$-anchoring a necessary condition for reliable detection of high-ability models at high contamination.
57	
58	ARC-C reverses this pattern.
59	Despite Qwen's high baseline accuracy on ARC-C (89.7\%), contamination produces larger, not smaller, effect sizes ($|d|{=}3.16$ at 15\%, $|d|{=}5.30$ at 50\%).
60	This reversal reflects a ceiling effect: with only 295 items and 89.7\% baseline accuracy, the already-correct items offer minimal room for further $\theta$ inflation, so contamination manifests primarily as anomalous successes on the few remaining hard items.
61	The small item count amplifies this concentration, producing a disproportionately large $\ell_z^*$ shift per contaminated item.
62	
63	The baseline $\ell_z^*$ for ARC-C is negative ($-5.42$), reflecting the 4PL model's expectation of near-perfect performance; contamination pushes $\ell_z^*$ toward zero, producing the positive Cohen's $d$ values in Table~\ref{tab:cohens_d}.
64	
65	These findings indicate that detection sensitivity is not a fixed property of $\ell_z^*$ but depends on the interaction between model ability and benchmark characteristics, a consideration absent from standard person-fit applications.
66	
67	\paragraph{Fixed-$\theta$ estimation.}
68	Table~\ref{tab:theta_fixed} compares free-$\theta$ and fixed-$\theta$ Cohen's $d$ across all three families.
69	The benefit of fixed-$\theta$ is modulated by baseline $\ell_z^*$ level rather than $\theta$-shift magnitude.
70	Qwen (67.8\% accuracy, $\Delta\theta{=}0.47$, baseline $\ell_z^*{=}{+}8.68$) shows 2.4$\times$ amplification at 50\%: its large baseline departure from the IRT null provides substantial signal that free-$\theta$ absorption erodes, which $\theta$-anchoring recovers (multi-seed mean ${\ell_z^*}_{\text{fixed}} {=} 14.5$ vs.\ clean $7.35$).
71	Mistral (52.4\%, baseline $\ell_z^*{=}{+}4.02$) shows 1.7$\times$ at 50\%.
72	Llama (59.4\%, $\Delta\theta{=}0.39$ at 15\%, $0.52$ at 50\%) shows 0.4$\times$ at 50\% despite comparable $\theta$-shift: its near-zero baseline $\ell_z^*$ ($+0.26$) indicates that the clean response pattern conforms to IRT expectations, leaving no absorbed signal for $\theta$-anchoring to recover.
73	The amplification ratio tracks baseline $|\ell_z^*|$ monotonically ($8.68 {\to} 2.4{\times}$; $4.02 {\to} 1.7{\times}$; $0.26 {\to} 0.4{\times}$ at 50\%), making fixed-$\theta$ a targeted remedy for models with substantial baseline misfit, not a universal one.
74	
75	\begin{table}[t]
76	\centering
77	\caption{Free-$\theta$ vs.\ fixed-$\theta$ Cohen's $|d|$ on MMLU (bootstrap 95\% CI). Fixed-$\theta$ anchors $\hat{\theta}$ at the clean-model mean, eliminating $\theta$-shift absorption.}
78	\label{tab:theta_fixed}
79	\footnotesize
80	\resizebox{\columnwidth}{!}{%
81	\begin{tabular}{@{}lcccc@{}}
82	\toprule
83	Model & $|d_{\text{free}}|$ & $|d_{\text{fixed}}|$ & Ratio (fixed/free) & Fixed CI \\
84	\midrule
85	\multicolumn{5}{@{}l}{\textit{5\% contamination}} \\
86	Qwen & 4.15 & 3.52 & 0.8$\times$ & [2.9, 5.7] \\
87	\addlinespace
88	\multicolumn{5}{@{}l}{\textit{15\% contamination}} \\
89	Qwen$^{\S}$ & 5.36 & 6.85 & 1.3$\times$ & ($\pm$1.80) \\
90	Llama & 2.11 & 0.58 & 0.3$\times$ & [0, 2.37]$^{\dagger}$ \\
91	Mistral$^{\ddagger}$ & 2.64 & 2.69 & 1.0$\times$ & [1.53, 9.06] \\
92	\addlinespace
93	\multicolumn{5}{@{}l}{\textit{50\% contamination}} \\
94	Qwen$^{\S}$ & 5.08 & 12.32 & 2.4$\times$ & ($\pm$2.38) \\
95	Llama & 2.33 & 0.84 & 0.4$\times$ & [0.17, 2.97] \\
96	Mistral$^{\ddagger}$ & 3.50 & 5.80 & 1.7$\times$ & [3.87, 18.45] \\
97	\bottomrule
98	\multicolumn{5}{@{}l}{\scriptsize $^{\dagger}$CI includes zero.} \\
99	\multicolumn{5}{@{}l}{\scriptsize $^{\S}$Multi-seed mean ($n{=}3$); CI column shows $\pm$SD of fixed-$\theta$ $|d|$.} \\
100	\multicolumn{5}{@{}l}{\scriptsize $^{\ddagger}$Fixed-$\theta$: 6 seeds (4 response vectors from seeds 4--7 not retained in pipeline); free-$\theta$ uses all 10.} \\
101	\multicolumn{5}{@{}p{0.9\columnwidth}}{\scriptsize $d_{\text{free}}$ values for single-seed conditions are from seed 42; multi-seed means are reported in Table~\ref{tab:cohens_d}.}
102	\end{tabular}}
103	\end{table}
104	
105	\begin{figure}[t]
106	  \centering
107	  \includegraphics[width=\columnwidth]{fig_theta_scatter.pdf}
108	  \caption{Baseline accuracy vs.\ Cohen's $|d|$ for all model-benchmark combinations (multi-seed means where available; per-seed values in Appendix~\ref{app:reproducibility}). Diamonds: 5\%; triangles: 15\%; squares: 25\%; circles: 50\%. ARC-C reversal reflects a ceiling effect.}
109	  \label{fig:theta_scatter}
110	\end{figure}
111	
112	\subsection{Detection-Diagnosis Tradeoff}
113	\label{sec:degradation}
114	
115	Having established that $\theta$-shift complicates detection, we ask whether the full 4PL framework is necessary, or whether simpler statistics suffice.
116	Table~\ref{tab:degradation} compares three statistics at decreasing levels of information access: $\ell_z^*$ (requires 4PL parameters $a, b, c, d$), the HT statistic (requires only difficulty $b$), and an accuracy $z$-score (requires no item parameters).
117	
118	The comparison reveals a detection-diagnosis tradeoff.
119	For pure detection, simpler statistics are more powerful: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics (Table~\ref{tab:degradation}), because cross-seed accuracy variance is near-zero in controlled settings.
120	HT generally exceeds $\ell_z^*$ in detection strength, since HT is not attenuated by the Snijders correction for $\theta$ estimation uncertainty.
121	Both person-fit statistics exhibit seed-dependent non-monotonicity under free-$\theta$ estimation (Table~\ref{tab:degradation}), confirming that $\theta$-shift absorption affects all statistics conditioned on ability, not $\ell_z^*$ specifically.
122	
123	Yet the diagnostic power reverses.
124	Full IRT parameterization is unnecessary for mere detection, but the value of $\ell_z^*$ lies in three capabilities that HT and $z$-scores lack:
125	(a) \emph{seen/unseen decomposition}: $\ell_z^*$ can be computed separately on seen and unseen item subsets, though item-level detection is near-random (AUROC $\approx 0.53$; Appendix~\ref{app:item_auroc}), confirming that the contamination signal is diffuse and requires model-level aggregation;
126	(b) \emph{$\theta$-shift mechanism}: the ability parameter exposes why detection sensitivity depends on model ability (\S\ref{sec:theta_dynamics}), a mechanistic insight inaccessible to non-parametric statistics;
127	(c) \emph{structural sensitivity}: on real leaderboard data, $\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\Delta\ell_z^*$ matched-difference design (\S\ref{sec:did}; Appendix~\ref{app:leaderboard_aberrance}).
128	Accuracy $z$-scores flag only 4/60 cells, making them insensitive to the response-pattern structure that $\ell_z^*$ exploits for within-model diagnosis.
129	While such patterns have theoretical antecedents in person-fit literature \citep{stonge2011}, the specific magnitude and model-dependence we observe are new empirical findings in the LLM domain; nonparametric alternatives \citep{tendeiro2014} may complement $\ell_z^*$ where 4PL calibration is unavailable.
130	
131	In practice, a two-stage workflow follows: screen using accuracy $z$-scores (Table~\ref{tab:degradation}), then apply $\ell_z^*$ to characterize whether the signal reflects $\theta$-shift absorption (indicating fixed-$\theta$ anchoring is needed) or uniform aberrance (suggesting direct memorization).
132	
133	Within the IRT family, the 4PL specification matters: simulation ablations show a mean $+$27.3pp power gain over 3PL on MMLU, because 46\% of MMLU items have upper asymptote $d < 0.95$, and the 3PL model (which assumes $d{=}1$) misattributes slip-related response patterns as aberrance (Appendix~\ref{app:4pl_ablation}).
134	
135	\begin{table}[t]
136	\centering
137	\caption{Detection-diagnosis tradeoff on MMLU: Cohen's $|d|$ across three statistics. Simpler statistics detect more powerfully; $\ell_z^*$ provides unique diagnostic capabilities (\S\ref{sec:degradation}).}
138	\label{tab:degradation}
139	\footnotesize
140	\begin{tabular}{@{}llrr@{}}
141	\toprule
142	Model & Statistic & $|d|$ (15\%) & $|d|$ (50\%) \\
143	\midrule
144	Qwen$^\dagger$ & $\ell_z^*$ & $5.36$ ($\pm$1.10) & $5.08$ ($\pm$3.02) \\
145	     & HT & $5.83$ ($\pm$1.30) & $5.29$ ($\pm$3.41) \\
146	     & Acc.\ $z$ & $45.0$ ($\pm$2.5) & $70.0$ ($\pm$1.1) \\
147	\addlinespace
148	Llama & $\ell_z^*$ & $2.11$ [$1.4$, $4.8$] & $2.33$ [$1.6$, $5.1$] \\
149	      & HT & $2.45$ [$1.5$, $4.3$] & $3.07$ [$1.9$, $5.3$] \\
150	      & Acc.\ $z$ & $22.5$ [$13.6$, $47.0$] & $32.8$ [$19.8$, $68.6$] \\
151	\addlinespace
152	Mistral$^\dagger$ & $\ell_z^*$ & $3.37$ ($\pm$0.68) & $4.09$ ($\pm$0.53) \\
153	      & HT & $4.36$ [$1.2$, $7.0$] & $5.89$ [$1.9$, $9.4$] \\
154	      & Acc.\ $z$ & $7.81$ [$4.4$, $14.4$] & $16.6$ [$9.7$, $34.6$] \\
155	\bottomrule
156	\multicolumn{4}{@{}p{0.9\columnwidth}}{\scriptsize $^\dagger$Multi-seed values are means across $n{=}3$ independent runs; per-seed values in Appendix~\ref{app:reproducibility}. Remaining conditions are single-seed with bootstrap CIs.}
157	\end{tabular}
158	\end{table}
159	
160	\subsection{Ability-Dependent Non-Monotonic Dose-Response}
161	\label{sec:inverted_u}
162	
163	As an exploratory observation, the free-$\theta$ dose-response is non-monotonic for Qwen.
164	Figure~\ref{fig:dose_response} plots the multi-seed mean trajectory ($|d|$: $4.15 \to 5.36 \to 7.44 \to 5.08$ at 5\%/15\%/25\%/50\%; Appendix~\ref{app:reproducibility}), showing signal peaking at 25\% before declining at 50\%; the decline is attenuated relative to single-seed estimates and the inter-seed variance at 50\% is high (CV${=}$60\%, range $[1.90, 7.91]$).
165	
166	\begin{figure}[t]
167	  \centering
168	  \includegraphics[width=\columnwidth]{fig_dose_response.pdf}
169	  \caption{Dose-response trajectories for Cohen's $|d|$ on MMLU. Qwen free-$\theta$ (circles) exhibits non-monotonic behavior---signal peaks at 25\% then declines as $\theta$-shift absorbs the aberrance. Fixed-$\theta$ anchoring (squares, dashed) eliminates the artifact and reveals monotonic dose-response. Llama (triangles) shows a flat trajectory. Error bars: $\pm$1\,SD across $n{=}3$ training seeds; bands: $\pm$1\,SD envelope. Hollow markers at 5\%: single-seed.}
170	  \label{fig:dose_response}
171	\end{figure}
172	This non-monotonicity is a $\theta$-estimation artifact: fixed-$\theta$ analysis eliminates the inverted-U and reveals a strong positive dose-response (mean $|d|$: $5.89$ at 25\% vs.\ $12.32$ at 50\%, no seed-level overlap), while reducing the 50\% CV to 19\%.
173	Llama shows an approximately flat dose-response ($|d|{=}2.80 \to 2.56 \to 2.30$), consistent with its near-zero $\ell_z^*$ baseline ($+0.26$ vs.\ ${+}8.68$ for Qwen) despite comparable $\theta$-shift ($\Delta\theta{=}0.52$ vs.\ $0.47$).
174	The mechanism is predictable from simulation (Appendix~\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\hat{\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.
175	Three regimes are visible in Qwen's free-$\theta$ trajectory: at 5\%, $\theta$-shift is negligible and $\ell_z^*$ captures the full misfit; through 15--25\%, pattern deviations outpace $\theta$-shift absorption, yielding peak signal; at 50\%, $\Delta\theta{=}0.47$ absorbs enough aberrance that $|d|$ declines despite double the contamination fraction.
176	
177	A simulated power analysis corroborates these findings: two-sided testing (flagging both large negative and large positive $\ell_z^*$) achieves ${>}$93\% power on MMLU at all contamination levels, with the theoretical power function yielding $R^2 {=} 0.957$ against simulated values (Appendix~\ref{app:simulation}).
178	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b6bd479c-e236-487d-bc4f-8c1ddc1410e6",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "3a3fdcf1-0833-426b-8d94-5899750f147a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex",
      "content": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Detection Signal Across Model Families}\n\\label{sec:detection}\n\nTable~\\ref{tab:cohens_d} presents Cohen's $d$ effect sizes for $\\ell_z^*$ across three model families and two benchmarks.\nAll confidence intervals exclude zero, confirming that $\\Delta\\ell_z^*$ reliably separates contaminated from clean models at both contamination levels.\n\nOn MMLU, effect sizes range from $|d|{=}2.30$ (Llama at 50\\%) to $|d|{=}7.44$ (Qwen at 25\\%), with Qwen at 5\\% ($|d|{=}4.15$) confirming detection at the lowest contamination level tested. Llama ($|d|{=}2.80$/$2.56$/$2.30$) and Mistral ($|d|{=}3.37$/$4.09$) show comparable magnitudes.\nOn ARC-C (295 items), Qwen yields $|d|{=}3.16$ at 15\\% and $|d|{=}5.30$ at 50\\%, demonstrating that detection remains feasible even on small benchmarks when contamination is sufficiently concentrated.\n\nClean-model $\\ell_z^*$ baselines diverge substantially across families: Qwen ${+}8.68$ ($\\text{SD}{=}0.74$), Mistral ${+}4.02$ ($\\text{SD}{=}2.05$), Llama ${+}0.26$ ($\\text{SD}{=}1.54$), and ARC-C Qwen ${-}5.42$ ($\\text{SD}{=}0.16$); this divergence reflects difficulty-ordering consistency rather than accuracy level (Appendix~\\ref{app:baseline_meaning}).\nAbsolute $\\ell_z^*$ thresholds would produce contradictory results: Qwen's contaminated $\\ell_z^*$ at 15\\% (${+}3.8$) is still positive.\nThe $\\Delta\\ell_z^*$ design normalizes these divergent baselines: Cohen's $d$ yields comparable effect sizes ($|d|{=}2.30$--$7.44$) despite order-of-magnitude differences.\nFigure~\\ref{fig:heatmap} provides a visual summary.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cohen's $d$ for $\\Delta\\ell_z^*$ across model families ($n{=}10$ clean seeds). Single-seed conditions: percentile bootstrap 95\\% CI (10,000 resamples). $^{\\dagger}$Multi-seed conditions: mean $\\pm$ SD ($n{=}3$ independent runs). All CIs exclude zero.}\n\\label{tab:cohens_d}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrrrr@{}}\n\\toprule\nModel & Bench. & $d$ (5\\%) [CI] & $d$ (15\\%) [CI] & $d$ (25\\%) [CI] & $d$ (50\\%) [CI] \\\\\n\\midrule\nQwen$^{\\dagger}$ & MMLU & $-4.15$ [$-9.9$, $-2.7$] & $-5.36$ ($\\pm$1.10) & $-7.44$ ($\\pm$1.86) & $-5.08$ ($\\pm$3.02) \\\\\nLlama$^{\\dagger}$ & MMLU & --- & $-2.80$ ($\\pm$0.60) & $-2.56$ ($\\pm$0.52) & $-2.30$ ($\\pm$0.30) \\\\\nMistral$^{\\dagger}$ & MMLU & --- & $-3.37$ ($\\pm$0.68) & --- & $-4.09$ ($\\pm$0.53) \\\\\nQwen$^{\\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\\\\n\\bottomrule\n\\multicolumn{6}{@{}l}{\\scriptsize $^{\\dagger}$Multi-seed conditions: means ($n{=}3$ independent runs) shown as $\\pm$SD; remaining conditions are single-seed with bootstrap CIs. Per-seed values in Appendix~\\ref{app:reproducibility}.}\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure*}[t]\n  \\centering\n  \\includegraphics[width=\\textwidth]{fig_heatmap.pdf}\n  \\caption{Cohen's $|d|$ heatmap (values from Table~\\ref{tab:cohens_d}; multi-seed means where available). Blue intensity reflects effect-size magnitude. Grey cells: conditions not tested.}\n  \\label{fig:heatmap}\n\\end{figure*}\n\n\\subsection{Model-Specific $\\theta$-Shift Dynamics}\n\\label{sec:theta_dynamics}\n\nThe cross-family variation in Table~\\ref{tab:cohens_d}---Qwen's $|d|$ declining from 25\\% to 50\\% while Llama's remains flat---suggests detection sensitivity depends on more than contamination dose.\nContamination raises overall accuracy, which inflates $\\hat{\\theta}_{\\text{MLE}}$; a higher $\\hat{\\theta}$ ``explains away'' anomalous successes on hard items, absorbing the contamination signal into the ability estimate.\nWe term this \\emph{$\\theta$-shift absorption}.\nThe magnitude of $\\theta$-shift is comparable across families---Qwen ($\\Delta\\theta{=}0.47$ at 50\\%) and Llama ($\\Delta\\theta{=}0.52$)---yet their fixed-$\\theta$ amplification diverges markedly (Table~\\ref{tab:theta_fixed}), indicating that $\\theta$-shift magnitude alone does not predict fixed-$\\theta$ benefit.\nFigure~\\ref{fig:theta_scatter} plots baseline accuracy against Cohen's $|d|$ for all model-benchmark combinations.\n\n$\\theta$-shift absorption is the dominant source of detection variability for high-ability models at high contamination:\n(i) fixed-$\\theta$ estimation amplifies Qwen's multi-seed $|d|$ by 2.4$\\times$ at 50\\% ($5.08 \\to 12.32$; Table~\\ref{tab:theta_fixed}), while Llama shows no amplification ($0.4\\times$);\n(ii) $\\theta$-anchoring reduces Qwen's inter-seed CV from 60\\% to 19\\%, confirming that training-run variance is driven by $\\theta$-shift stochasticity rather than true signal variance;\n(iii) the cross-model ranking under free-$\\theta$ is seed-dependent at 50\\%, making $\\theta$-anchoring a necessary condition for reliable detection of high-ability models at high contamination.\n\nARC-C reverses this pattern.\nDespite Qwen's high baseline accuracy on ARC-C (89.7\\%), contamination produces larger, not smaller, effect sizes ($|d|{=}3.16$ at 15\\%, $|d|{=}5.30$ at 50\\%).\nThis reversal reflects a ceiling effect: with only 295 items and 89.7\\% baseline accuracy, the already-correct items offer minimal room for further $\\theta$ inflation, so contamination manifests primarily as anomalous successes on the few remaining hard items.\nThe small item count amplifies this concentration, producing a disproportionately large $\\ell_z^*$ shift per contaminated item.\n\nThe baseline $\\ell_z^*$ for ARC-C is negative ($-5.42$), reflecting the 4PL model's expectation of near-perfect performance; contamination pushes $\\ell_z^*$ toward zero, producing the positive Cohen's $d$ values in Table~\\ref{tab:cohens_d}.\n\nThese findings indicate that detection sensitivity is not a fixed property of $\\ell_z^*$ but depends on the interaction between model ability and benchmark characteristics, a consideration absent from standard person-fit applications.\n\n\\paragraph{Fixed-$\\theta$ estimation.}\nTable~\\ref{tab:theta_fixed} compares free-$\\theta$ and fixed-$\\theta$ Cohen's $d$ across all three families.\nThe benefit of fixed-$\\theta$ is modulated by baseline $\\ell_z^*$ level rather than $\\theta$-shift magnitude.\nQwen (67.8\\% accuracy, $\\Delta\\theta{=}0.47$, baseline $\\ell_z^*{=}{+}8.68$) shows 2.4$\\times$ amplification at 50\\%: its large baseline departure from the IRT null provides substantial signal that free-$\\theta$ absorption erodes, which $\\theta$-anchoring recovers (multi-seed mean ${\\ell_z^*}_{\\text{fixed}} {=} 14.5$ vs.\\ clean $7.35$).\nMistral (52.4\\%, baseline $\\ell_z^*{=}{+}4.02$) shows 1.7$\\times$ at 50\\%.\nLlama (59.4\\%, $\\Delta\\theta{=}0.39$ at 15\\%, $0.52$ at 50\\%) shows 0.4$\\times$ at 50\\% despite comparable $\\theta$-shift: its near-zero baseline $\\ell_z^*$ ($+0.26$) indicates that the clean response pattern conforms to IRT expectations, leaving no absorbed signal for $\\theta$-anchoring to recover.\nThe amplification ratio tracks baseline $|\\ell_z^*|$ monotonically ($8.68 {\\to} 2.4{\\times}$; $4.02 {\\to} 1.7{\\times}$; $0.26 {\\to} 0.4{\\times}$ at 50\\%), making fixed-$\\theta$ a targeted remedy for models with substantial baseline misfit, not a universal one.\n\n\\begin{table}[t]\n\\centering\n\\caption{Free-$\\theta$ vs.\\ fixed-$\\theta$ Cohen's $|d|$ on MMLU (bootstrap 95\\% CI). Fixed-$\\theta$ anchors $\\hat{\\theta}$ at the clean-model mean, eliminating $\\theta$-shift absorption.}\n\\label{tab:theta_fixed}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nModel & $|d_{\\text{free}}|$ & $|d_{\\text{fixed}}|$ & Ratio (fixed/free) & Fixed CI \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{5\\% contamination}} \\\\\nQwen & 4.15 & 3.52 & 0.8$\\times$ & [2.9, 5.7] \\\\\n\\addlinespace\n\\multicolumn{5}{@{}l}{\\textit{15\\% contamination}} \\\\\nQwen$^{\\S}$ & 5.36 & 6.85 & 1.3$\\times$ & ($\\pm$1.80) \\\\\nLlama & 2.11 & 0.58 & 0.3$\\times$ & [0, 2.37]$^{\\dagger}$ \\\\\nMistral$^{\\ddagger}$ & 2.64 & 2.69 & 1.0$\\times$ & [1.53, 9.06] \\\\\n\\addlinespace\n\\multicolumn{5}{@{}l}{\\textit{50\\% contamination}} \\\\\nQwen$^{\\S}$ & 5.08 & 12.32 & 2.4$\\times$ & ($\\pm$2.38) \\\\\nLlama & 2.33 & 0.84 & 0.4$\\times$ & [0.17, 2.97] \\\\\nMistral$^{\\ddagger}$ & 3.50 & 5.80 & 1.7$\\times$ & [3.87, 18.45] \\\\\n\\bottomrule\n\\multicolumn{5}{@{}l}{\\scriptsize $^{\\dagger}$CI includes zero.} \\\\\n\\multicolumn{5}{@{}l}{\\scriptsize $^{\\S}$Multi-seed mean ($n{=}3$); CI column shows $\\pm$SD of fixed-$\\theta$ $|d|$.} \\\\\n\\multicolumn{5}{@{}l}{\\scriptsize $^{\\ddagger}$Fixed-$\\theta$: 6 seeds (4 response vectors from seeds 4--7 not retained in pipeline); free-$\\theta$ uses all 10.} \\\\\n\\multicolumn{5}{@{}p{0.9\\columnwidth}}{\\scriptsize $d_{\\text{free}}$ values for single-seed conditions are from seed 42; multi-seed means are reported in Table~\\ref{tab:cohens_d}.}\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_theta_scatter.pdf}\n  \\caption{Baseline accuracy vs.\\ Cohen's $|d|$ for all model-benchmark combinations (multi-seed means where available; per-seed values in Appendix~\\ref{app:reproducibility}). Diamonds: 5\\%; triangles: 15\\%; squares: 25\\%; circles: 50\\%. ARC-C reversal reflects a ceiling effect.}\n  \\label{fig:theta_scatter}\n\\end{figure}\n\n\\subsection{Detection-Diagnosis Tradeoff}\n\\label{sec:degradation}\n\nHaving established that $\\theta$-shift complicates detection, we ask whether the full 4PL framework is necessary, or whether simpler statistics suffice.\nTable~\\ref{tab:degradation} compares three statistics at decreasing levels of information access: $\\ell_z^*$ (requires 4PL parameters $a, b, c, d$), the HT statistic (requires only difficulty $b$), and an accuracy $z$-score (requires no item parameters).\n\nThe comparison reveals a detection-diagnosis tradeoff.\nFor pure detection, simpler statistics are more powerful: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics (Table~\\ref{tab:degradation}), because cross-seed accuracy variance is near-zero in controlled settings.\nHT generally exceeds $\\ell_z^*$ in detection strength, since HT is not attenuated by the Snijders correction for $\\theta$ estimation uncertainty.\nBoth person-fit statistics exhibit seed-dependent non-monotonicity under free-$\\theta$ estimation (Table~\\ref{tab:degradation}), confirming that $\\theta$-shift absorption affects all statistics conditioned on ability, not $\\ell_z^*$ specifically.\n\nYet the diagnostic power reverses.\nFull IRT parameterization is unnecessary for mere detection, but the value of $\\ell_z^*$ lies in three capabilities that HT and $z$-scores lack:\n(a) \\emph{seen/unseen decomposition}: $\\ell_z^*$ can be computed separately on seen and unseen item subsets, though item-level detection is near-random (AUROC $\\approx 0.53$; Appendix~\\ref{app:item_auroc}), confirming that the contamination signal is diffuse and requires model-level aggregation;\n(b) \\emph{$\\theta$-shift mechanism}: the ability parameter exposes why detection sensitivity depends on model ability (\\S\\ref{sec:theta_dynamics}), a mechanistic insight inaccessible to non-parametric statistics;\n(c) \\emph{structural sensitivity}: on real leaderboard data, $\\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\\Delta\\ell_z^*$ matched-difference design (\\S\\ref{sec:did}; Appendix~\\ref{app:leaderboard_aberrance}).\nAccuracy $z$-scores flag only 4/60 cells, making them insensitive to the response-pattern structure that $\\ell_z^*$ exploits for within-model diagnosis.\nWhile such patterns have theoretical antecedents in person-fit literature \\citep{stonge2011}, the specific magnitude and model-dependence we observe are new empirical findings in the LLM domain; nonparametric alternatives \\citep{tendeiro2014} may complement $\\ell_z^*$ where 4PL calibration is unavailable.\n\nIn practice, a two-stage workflow follows: screen using accuracy $z$-scores (Table~\\ref{tab:degradation}), then apply $\\ell_z^*$ to characterize whether the signal reflects $\\theta$-shift absorption (indicating fixed-$\\theta$ anchoring is needed) or uniform aberrance (suggesting direct memorization).\n\nWithin the IRT family, the 4PL specification matters: simulation ablations show a mean $+$27.3pp power gain over 3PL on MMLU, because 46\\% of MMLU items have upper asymptote $d < 0.95$, and the 3PL model (which assumes $d{=}1$) misattributes slip-related response patterns as aberrance (Appendix~\\ref{app:4pl_ablation}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Detection-diagnosis tradeoff on MMLU: Cohen's $|d|$ across three statistics. Simpler statistics detect more powerfully; $\\ell_z^*$ provides unique diagnostic capabilities (\\S\\ref{sec:degradation}).}\n\\label{tab:degradation}\n\\footnotesize\n\\begin{tabular}{@{}llrr@{}}\n\\toprule\nModel & Statistic & $|d|$ (15\\%) & $|d|$ (50\\%) \\\\\n\\midrule\nQwen$^\\dagger$ & $\\ell_z^*$ & $5.36$ ($\\pm$1.10) & $5.08$ ($\\pm$3.02) \\\\\n     & HT & $5.83$ ($\\pm$1.30) & $5.29$ ($\\pm$3.41) \\\\\n     & Acc.\\ $z$ & $45.0$ ($\\pm$2.5) & $70.0$ ($\\pm$1.1) \\\\\n\\addlinespace\nLlama & $\\ell_z^*$ & $2.11$ [$1.4$, $4.8$] & $2.33$ [$1.6$, $5.1$] \\\\\n      & HT & $2.45$ [$1.5$, $4.3$] & $3.07$ [$1.9$, $5.3$] \\\\\n      & Acc.\\ $z$ & $22.5$ [$13.6$, $47.0$] & $32.8$ [$19.8$, $68.6$] \\\\\n\\addlinespace\nMistral$^\\dagger$ & $\\ell_z^*$ & $3.37$ ($\\pm$0.68) & $4.09$ ($\\pm$0.53) \\\\\n      & HT & $4.36$ [$1.2$, $7.0$] & $5.89$ [$1.9$, $9.4$] \\\\\n      & Acc.\\ $z$ & $7.81$ [$4.4$, $14.4$] & $16.6$ [$9.7$, $34.6$] \\\\\n\\bottomrule\n\\multicolumn{4}{@{}p{0.9\\columnwidth}}{\\scriptsize $^\\dagger$Multi-seed values are means across $n{=}3$ independent runs; per-seed values in Appendix~\\ref{app:reproducibility}. Remaining conditions are single-seed with bootstrap CIs.}\n\\end{tabular}\n\\end{table}\n\n\\subsection{Ability-Dependent Non-Monotonic Dose-Response}\n\\label{sec:inverted_u}\n\nAs an exploratory observation, the free-$\\theta$ dose-response is non-monotonic for Qwen.\nFigure~\\ref{fig:dose_response} plots the multi-seed mean trajectory ($|d|$: $4.15 \\to 5.36 \\to 7.44 \\to 5.08$ at 5\\%/15\\%/25\\%/50\\%; Appendix~\\ref{app:reproducibility}), showing signal peaking at 25\\% before declining at 50\\%; the decline is attenuated relative to single-seed estimates and the inter-seed variance at 50\\% is high (CV${=}$60\\%, range $[1.90, 7.91]$).\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_dose_response.pdf}\n  \\caption{Dose-response trajectories for Cohen's $|d|$ on MMLU. Qwen free-$\\theta$ (circles) exhibits non-monotonic behavior---signal peaks at 25\\% then declines as $\\theta$-shift absorbs the aberrance. Fixed-$\\theta$ anchoring (squares, dashed) eliminates the artifact and reveals monotonic dose-response. Llama (triangles) shows a flat trajectory. Error bars: $\\pm$1\\,SD across $n{=}3$ training seeds; bands: $\\pm$1\\,SD envelope. Hollow markers at 5\\%: single-seed.}\n  \\label{fig:dose_response}\n\\end{figure}\nThis non-monotonicity is a $\\theta$-estimation artifact: fixed-$\\theta$ analysis eliminates the inverted-U and reveals a strong positive dose-response (mean $|d|$: $5.89$ at 25\\% vs.\\ $12.32$ at 50\\%, no seed-level overlap), while reducing the 50\\% CV to 19\\%.\nLlama shows an approximately flat dose-response ($|d|{=}2.80 \\to 2.56 \\to 2.30$), consistent with its near-zero $\\ell_z^*$ baseline ($+0.26$ vs.\\ ${+}8.68$ for Qwen) despite comparable $\\theta$-shift ($\\Delta\\theta{=}0.52$ vs.\\ $0.47$).\nThe mechanism is predictable from simulation (Appendix~\\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\\hat{\\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.\nThree regimes are visible in Qwen's free-$\\theta$ trajectory: at 5\\%, $\\theta$-shift is negligible and $\\ell_z^*$ captures the full misfit; through 15--25\\%, pattern deviations outpace $\\theta$-shift absorption, yielding peak signal; at 50\\%, $\\Delta\\theta{=}0.47$ absorbs enough aberrance that $|d|$ declines despite double the contamination fraction.\n\nA simulated power analysis corroborates these findings: two-sided testing (flagging both large negative and large positive $\\ell_z^*$) achieves ${>}$93\\% power on MMLU at all contamination levels, with the theoretical power function yielding $R^2 {=} 0.957$ against simulated values (Appendix~\\ref{app:simulation}).\n",
      "numLines": 178,
      "startLine": 1,
      "totalLines": 178
    }
  },
  "sourceToolAssistantUUID": "b6bd479c-e236-487d-bc4f-8c1ddc1410e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-24T12:17:18.114Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HBmr4cTck28GhGL3rbcgWa`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3a3fdcf1-0833-426b-8d94-5899750f147a",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "263d7797-7f69-4de6-ad9b-f82ba07b8bde",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 35 · 2026-05-24T12:17:18.119Z_

<details><summary>↩ Tool result · `toolu_01HBmr4cTck28GhGL3rbcgWa`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	Our findings reveal both the strengths and boundaries of IRT person-fit for contamination detection: $\ell_z^*$ reliably detects SFT-stage contamination across model families, but three boundary conditions constrain its practical utility.
4	
5	\paragraph{Characterization over tool.}
6	The detection-diagnosis tradeoff (\S\ref{sec:degradation}) shows that simpler statistics detect contamination more powerfully than $\ell_z^*$: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger, and HT generally exceeds $\ell_z^*$.
7	The value of the IRT framework lies not in detection power but in mechanistic understanding: the $\theta$-shift analysis reveals \emph{why} detection sensitivity varies across models and contamination levels, the seen/unseen decomposition identifies \emph{what fraction} of items are memorized, and the 4PL parameterization captures item-level ceiling effects that 3PL misattributes as aberrance.
8	These diagnostics are invisible to accuracy $z$-scores or HT; our contribution lies in quantifying these theoretically predictable effects in the LLM setting, where magnitudes and boundary conditions are not derivable from theory alone.
9	
10	\paragraph{Practical implications.}
11	Two results have immediate consequences.
12	Free-$\theta$ estimation produces seed-dependent dose-response curves (CV up to 60\%); $\theta$-anchoring stabilizes detection for models whose clean $\ell_z^*$ departs substantially from zero.
13	$\ell_z^*$ is most informative for large benchmarks ($n \approx 8{,}000$ items for 80\% power at 15\% contamination); on small benchmarks like ARC-C, detection relies on concentrated contamination effects.
14	
15	\paragraph{Scope and calibration.}
16	Universal baseline misfit (57/60 cells flagged) confirms systematic IRT violations; the $\Delta\ell_z^*$ design turns this into a feature through within-model differencing.
17	PSN-IRT provides pre-calibrated 4PL parameters \citep{psnirt2026}, but classical calibration fails on contaminated data ($r_a{=}0.127$; Appendix~\ref{app:mml_em}); the robustness analysis (Appendix~\ref{app:param_perturb}) provides partial reassurance (${\pm}10\%$ noise tolerance).
18	\paragraph{Information requirements and method positioning.}
19	$\ell_z^*$ sits below MIA \citep[logits;][]{minkprob2024} and ConStat \citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot confirms this: Min-K\% AUC drops to chance ($0.493$) post-RL while $\ell_z^*$ signal persists (${\sim}3.3$; Figure~\ref{fig:grpo}), consistent with \citet{wang2025fragility}.
20	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "263d7797-7f69-4de6-ad9b-f82ba07b8bde",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "3e1e3dbb-13d5-4d11-b488-afd33bf40ce6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\nOur findings reveal both the strengths and boundaries of IRT person-fit for contamination detection: $\\ell_z^*$ reliably detects SFT-stage contamination across model families, but three boundary conditions constrain its practical utility.\n\n\\paragraph{Characterization over tool.}\nThe detection-diagnosis tradeoff (\\S\\ref{sec:degradation}) shows that simpler statistics detect contamination more powerfully than $\\ell_z^*$: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger, and HT generally exceeds $\\ell_z^*$.\nThe value of the IRT framework lies not in detection power but in mechanistic understanding: the $\\theta$-shift analysis reveals \\emph{why} detection sensitivity varies across models and contamination levels, the seen/unseen decomposition identifies \\emph{what fraction} of items are memorized, and the 4PL parameterization captures item-level ceiling effects that 3PL misattributes as aberrance.\nThese diagnostics are invisible to accuracy $z$-scores or HT; our contribution lies in quantifying these theoretically predictable effects in the LLM setting, where magnitudes and boundary conditions are not derivable from theory alone.\n\n\\paragraph{Practical implications.}\nTwo results have immediate consequences.\nFree-$\\theta$ estimation produces seed-dependent dose-response curves (CV up to 60\\%); $\\theta$-anchoring stabilizes detection for models whose clean $\\ell_z^*$ departs substantially from zero.\n$\\ell_z^*$ is most informative for large benchmarks ($n \\approx 8{,}000$ items for 80\\% power at 15\\% contamination); on small benchmarks like ARC-C, detection relies on concentrated contamination effects.\n\n\\paragraph{Scope and calibration.}\nUniversal baseline misfit (57/60 cells flagged) confirms systematic IRT violations; the $\\Delta\\ell_z^*$ design turns this into a feature through within-model differencing.\nPSN-IRT provides pre-calibrated 4PL parameters \\citep{psnirt2026}, but classical calibration fails on contaminated data ($r_a{=}0.127$; Appendix~\\ref{app:mml_em}); the robustness analysis (Appendix~\\ref{app:param_perturb}) provides partial reassurance (${\\pm}10\\%$ noise tolerance).\n\\paragraph{Information requirements and method positioning.}\n$\\ell_z^*$ sits below MIA \\citep[logits;][]{minkprob2024} and ConStat \\citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot confirms this: Min-K\\% AUC drops to chance ($0.493$) post-RL while $\\ell_z^*$ signal persists (${\\sim}3.3$; Figure~\\ref{fig:grpo}), consistent with \\citet{wang2025fragility}.\n",
      "numLines": 20,
      "startLine": 1,
      "totalLines": 20
    }
  },
  "sourceToolAssistantUUID": "263d7797-7f69-4de6-ad9b-f82ba07b8bde",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-24T12:17:19.035Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LvE2WzLrbG7N6mxJkDuAvw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3e1e3dbb-13d5-4d11-b488-afd33bf40ce6",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "1e34ce0a-0385-47d5-b0e9-9f5d4d79506e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 37 · 2026-05-24T12:17:19.039Z_

<details><summary>↩ Tool result · `toolu_01LvE2WzLrbG7N6mxJkDuAvw`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We characterized IRT person-fit statistics for LLM contamination detection across three 7--8B model families, establishing reliable SFT-stage detection while identifying boundary conditions: $\theta$-shift absorption necessitating $\theta$-anchored estimation for high-ability models, a detection-diagnosis tradeoff, and non-monotonic dose-response as a $\theta$-estimation artifact.
4	For practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \emph{which} items drive aberrance rather than merely flagging contamination.
5	Beyond detection, person-fit statistics capture response-pattern anomalies that persist after RL post-training erases memorization-based signals, complementing logit-based methods.
6	Future work should address pretraining-stage signatures, broader model scales, and cross-benchmark generalization with larger item banks.
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1e34ce0a-0385-47d5-b0e9-9f5d4d79506e",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "0662556e-7157-45e3-b426-0d1df645863e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe characterized IRT person-fit statistics for LLM contamination detection across three 7--8B model families, establishing reliable SFT-stage detection while identifying boundary conditions: $\\theta$-shift absorption necessitating $\\theta$-anchored estimation for high-ability models, a detection-diagnosis tradeoff, and non-monotonic dose-response as a $\\theta$-estimation artifact.\nFor practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \\emph{which} items drive aberrance rather than merely flagging contamination.\nBeyond detection, person-fit statistics capture response-pattern anomalies that persist after RL post-training erases memorization-based signals, complementing logit-based methods.\nFuture work should address pretraining-stage signatures, broader model scales, and cross-benchmark generalization with larger item banks.\n",
      "numLines": 7,
      "startLine": 1,
      "totalLines": 7
    }
  },
  "sourceToolAssistantUUID": "1e34ce0a-0385-47d5-b0e9-9f5d4d79506e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-24T12:17:19.533Z_

<details open><summary>🔧 Tool call — Read · `toolu_0188KAwjRRA1kmMBKqFScbKv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0662556e-7157-45e3-b426-0d1df645863e",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "5c26435f-cf9c-4ef8-87c3-c5ff32ead098",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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

_source line 39 · 2026-05-24T12:17:19.537Z_

<details><summary>↩ Tool result · `toolu_0188KAwjRRA1kmMBKqFScbKv`</summary>

```text
1	\section*{Limitations}
2	
3	Our controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.
4	Most contamination conditions use a single training run, and multi-seed replication (available for Qwen, Llama, and Mistral) reveals high seed dependence at 50\% contamination (CV${=}$60\%), partially resolved by $\theta$-anchoring; the post-RL characterization is $N{=}1$.
5	The framework depends on pre-calibrated 4PL item parameters from PSN-IRT, whose calibration sample may include contaminated models, and we do not provide head-to-head comparison with logit-based methods (MIA, ConStat) that operate at a different information level.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5c26435f-cf9c-4ef8-87c3-c5ff32ead098",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "698e0032-b0ed-466a-9b09-5f50004c7a2b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex",
      "content": "\\section*{Limitations}\n\nOur controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.\nMost contamination conditions use a single training run, and multi-seed replication (available for Qwen, Llama, and Mistral) reveals high seed dependence at 50\\% contamination (CV${=}$60\\%), partially resolved by $\\theta$-anchoring; the post-RL characterization is $N{=}1$.\nThe framework depends on pre-calibrated 4PL item parameters from PSN-IRT, whose calibration sample may include contaminated models, and we do not provide head-to-head comparison with logit-based methods (MIA, ConStat) that operate at a different information level.\n",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  },
  "sourceToolAssistantUUID": "5c26435f-cf9c-4ef8-87c3-c5ff32ead098",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-24T12:17:19.815Z_

<details open><summary>🔧 Tool call — Read · `toolu_014GfKYuAMDJ2aEG94My5uaQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "698e0032-b0ed-466a-9b09-5f50004c7a2b",
  "isSidechain": false,
  "requestId": "req_011CbMNwa3cX5WUosJpZTEMM",
  "type": "assistant",
  "uuid": "ca3108bc-cec3-4515-850e-15e6ea950c54",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174nrTwjac56gAaKmvSF5sy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 814,
      "cache_read_input_tokens": 52114,
      "output_tokens": 805,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 805,
          "cache_read_input_tokens": 52114,
          "cache_creation_input_tokens": 814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 814
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
  "lastPrompt": "项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper  Phase 1 确定性检查结果： 源码检查: passed=False, 1 critical, 1 warning 一致性检查:…",
  "leafUuid": "ca3108bc-cec3-4515-850e-15e6ea950c54",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 42_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Tool result

_source line 43 · 2026-05-24T12:17:20.109Z_

<details><summary>↩ Tool result · `toolu_014GfKYuAMDJ2aEG94My5uaQ`</summary>

```text
1	\section{Simulation Validation}
2	\label{app:simulation}
3	
4	Under the null (no contamination), bootstrap $\ell_z^*$ tracks $\mathcal{N}(0,1)$: mean bias 0.041 and standard deviation 1.003 on MMLU.
5	Kolmogorov--Smirnov rejection rates vary with benchmark size: 8.3\% for MMLU and HellaSwag ($n > 10{,}000$), 50.0\% for GSM8K ($n = 1{,}319$), 58.3\% for ARC-C ($n = 295$), and 75.0\% for HumanEval ($n = 164$).
6	$\ell_z^*$ is well-calibrated for benchmarks with $n \geq 10{,}000$ items; smaller benchmarks show increasing finite-sample deviations from normality.
7	
8	Two-sided testing eliminates the inverted-U artifact: MMLU achieves 97.8\% power at 15\% contamination and sustains ${>}$93\% at all levels.
9	Power scales with $\sqrt{n}$, as predicted by the noncentrality parameter $\delta \propto \sqrt{n}$.
10	The empirical power function, derived via Gauss--Hermite quadrature ($K=30$) over the ability distribution, achieves $R^2 = 0.957$ against simulated values, with approximate minimum benchmark size of $n \geq 7{,}958$ items for 80\% power at 15\% contamination under MMLU item parameters.
11	
12	\section{4PL vs.\ 3PL Ablation Details}
13	\label{app:4pl_ablation}
14	
15	Table~\ref{tab:4pl_3pl_power} reports detection power (proportion of 2{,}000 simulation replicates rejecting $H_0$ at $\alpha{=}0.05$, two-sided) for 4PL and 3PL parameterizations across five benchmarks and seven contamination levels.
16	The 4PL model yields higher power than 3PL at every non-trivial contamination level on every benchmark.
17	The advantage is largest on MMLU and HellaSwag, where upper-asymptote ($d < 1$) violations are most prevalent, and smallest on ARC-Challenge and HumanEval, where limited item counts constrain power under both parameterizations.
18	
19	Power is non-monotonic at 75\% contamination under 4PL on four of five benchmarks (e.g., MMLU: $.952 \to .938$; GSM8K: $.846 \to .802$).
20	This reflects the $\theta$-shift boundary condition described in \S\ref{sec:inverted_u}: at high contamination fractions, re-estimated $\hat{\theta}$ absorbs part of the aberrance signal, reducing $|\ell_z^*|$.
21	At 100\% contamination, all items are seen and power reaches 1.000 trivially.
22	The 4PL advantage over 3PL depends on accurate estimation of the upper asymptote $d$; with estimation error exceeding ${\sim}10\%$, the effective model behavior approaches 3PL ($d{=}1$) and the power gain diminishes.
23	PSN-IRT's large calibration sample ($12{+}$ models per item) typically yields $d$ standard errors well below this threshold.
24	
25	\begin{table*}[t]
26	\centering
27	\caption{Detection power (proportion rejecting $H_0$ at $\alpha{=}0.05$) under 4PL and 3PL parameterizations across benchmarks and contamination levels ($n{=}2{,}000$ replicates per cell). Bold indicates the 4PL advantage exceeds 5\,pp.}
28	\label{tab:4pl_3pl_power}
29	\small
30	\begin{tabular}{@{}llccccccc@{}}
31	\toprule
32	Benchmark & IRT & 5\% & 10\% & 15\% & 25\% & 50\% & 75\% & 100\% \\
33	\midrule
34	MMLU & 4PL & \textbf{.476} & \textbf{.848} & \textbf{.969} & \textbf{.983} & \textbf{.952} & \textbf{.938} & 1.00 \\
35	     & 3PL & .227 & .340 & .412 & .521 & .676 & .770 & 1.00 \\
36	\addlinespace
37	HellaSwag & 4PL & \textbf{.251} & \textbf{.454} & \textbf{.656} & \textbf{.915} & \textbf{.939} & \textbf{.919} & 1.00 \\
38	          & 3PL & .167 & .241 & .313 & .368 & .508 & .642 & 1.00 \\
39	\addlinespace
40	GSM8K & 4PL & \textbf{.156} & \textbf{.309} & \textbf{.492} & \textbf{.737} & \textbf{.846} & \textbf{.802} & 1.00 \\
41	      & 3PL & .102 & .172 & .285 & .396 & .567 & .577 & 1.00 \\
42	\addlinespace
43	ARC-C & 4PL & .057 & .075 & .087 & \textbf{.130} & \textbf{.285} & \textbf{.493} & 1.00 \\
44	      & 3PL & .054 & .062 & .071 & .076 & .110 & .102 & 1.00 \\
45	\addlinespace
46	HumanEval & 4PL & .076 & .121 & \textbf{.197} & \textbf{.302} & \textbf{.554} & \textbf{.521} & 1.00 \\
47	          & 3PL & .063 & .086 & .120 & .182 & .281 & .315 & 1.00 \\
48	\bottomrule
49	\end{tabular}
50	\end{table*}
51	
52	\section{Seed Sensitivity Analysis}
53	\label{app:seed_sensitivity}
54	
55	\paragraph{Clean-baseline variability.}
56	Table~\ref{tab:seed_sensitivity} reports $\ell_z^*$, accuracy, and $\hat{\theta}_{\text{MLE}}$ across three independent QLoRA runs (seeds 42, 123, 456).
57	For Qwen2.5-7B, $\ell_z^*$ ranges from $7.05$ (seed 123) to $9.53$ (seed 456); the lower value of seed 123 likely reflects seed-specific training dynamics (random initialization, data ordering), but all three seeds produce $\ell_z^* \gg 1.96$, confirming that the elevated baseline reflects systematic model--benchmark misfit rather than seed-specific artifacts.
58	Llama-3.1-8B shows $\ell_z^*$ near zero ($-0.14 \pm 0.97$), consistent with lower baseline misfit.
59	Accuracy variability is negligible for both families (CV $< 0.004$).
60	
61	\begin{table}[t]
62	\centering
63	\caption{Seed sensitivity analysis for clean baseline across three independent runs (seeds 42, 123, 456). CV = coefficient of variation ($\mathrm{std}/|\mathrm{mean}|$). These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \S\ref{sec:detection}; retained for methodological transparency.}
64	\label{tab:seed_sensitivity}
65	\footnotesize
66	\resizebox{\columnwidth}{!}{%
67	\begin{tabular}{@{}llcccc@{}}
68	\toprule
69	Model & Metric & Mean & Std & Range & CV \\
70	\midrule
71	Qwen2.5-7B & $\ell_z^*$ & 8.684 & 1.412 & 2.475 & 0.163 \\
72	 & Accuracy & 0.679 & 0.000 & 0.001 & 0.001 \\
73	 & $\hat{\theta}_{\mathrm{MLE}}$ & $-$0.097 & 0.012 & 0.023 & 0.119 \\
74	\midrule
75	Llama-3.1-8B & $\ell_z^*$ & $-$0.141 & 0.965 & 1.929 & 6.860 \\
76	 & Accuracy & 0.594 & 0.002 & 0.004 & 0.004 \\
77	 & $\hat{\theta}_{\mathrm{MLE}}$ & $-$0.645 & 0.019 & 0.036 & 0.029 \\
78	\bottomrule
79	\end{tabular}}
80	\end{table}
81	
82	\paragraph{Cohen's $d$ confidence intervals.}
83	Table~\ref{tab:cohens_d_ci} reports Cohen's $d$ effect sizes with both analytic and bootstrap 95\% confidence intervals.
84	Analytic CIs use $d \pm t_{0.025,\,\text{df}=2} \cdot \text{SE}_d$; with only $n{=}3$ clean seeds (df${=}2$), the critical value $t_{0.025,2} = 4.303$ produces intervals wide enough to cross zero in all four conditions.
85	This is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.
86	Bootstrap CIs (10{,}000 resamples with replacement from the three clean seeds) provide a nonparametric alternative: all four bootstrap intervals exclude zero, supporting the conclusion that contamination produces a reliably detectable signal despite the small reference sample.
87	
88	\begin{table}[t]
89	\centering
90	\caption{Cohen's $d$ with 95\% confidence intervals for contaminated conditions relative to clean baselines ($n{=}3$ seeds). Analytic CIs use $t_{0.025, \text{df}=2}$; bootstrap CIs use 10{,}000 resamples. These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \S\ref{sec:detection}; retained for methodological transparency.}
91	\label{tab:cohens_d_ci}
92	\footnotesize
93	\resizebox{\columnwidth}{!}{%
94	\begin{tabular}{@{}llccc@{}}
95	\toprule
96	Model & Cond. & $d$ & Analytic CI & Bootstrap CI \\
97	\midrule
98	Qwen & 15\% & $-$3.42 & [$-$9.92, 3.08] & [$-$3.45, $-$2.82] \\
99	 & 50\% & $-$0.99 & [$-$4.02, 2.04] & [$-$0.99, $-$0.41] \\
100	\midrule
101	Llama & 15\% & $-$2.95 & [$-$8.70, 2.80] & [$-$5.89, $-$2.29] \\
102	 & 50\% & $-$3.31 & [$-$9.63, 3.01] & [$-$6.47, $-$2.59] \\
103	\bottomrule
104	\end{tabular}}
105	\end{table}
106	
107	\paragraph{Cross-family consistency.}
108	Table~\ref{tab:cross_family} confirms that both model families produce large negative Cohen's $d$ under contamination.
109	The $|\Delta d| = 2.32$ gap at 50\% contamination reflects Qwen's non-monotonic dose-response (the $\theta$-shift boundary condition; \S\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.
110	
111	\begin{table}[t]
112	\centering
113	\caption{Cross-family consistency of contamination detection ($n{=}3$ pilot). Both families show large negative $d$ under contamination. Superseded by $n{=}10$ results in \S\ref{sec:detection}; retained for methodological transparency.}
114	\label{tab:cross_family}
115	\small
116	\begin{tabular}{@{}lcccl@{}}
117	\toprule
118	Condition & Qwen $d$ & Llama $d$ & $|\Delta d|$ & Consistent? \\
119	\midrule
120	15\% contam. & $-$3.42 & $-$2.95 & 0.47 & Yes \\
121	50\% contam. & $-$0.99 & $-$3.31 & 2.32 & Yes \\
122	\bottomrule
123	\end{tabular}
124	\end{table}
125	
126	\section{Baseline $\ell_z^*$ Interpretation}
127	\label{app:baseline_meaning}
128	
129	The baseline $\ell_z^*$ value reflects a model's difficulty-ordering consistency under the 4PL model, not its accuracy alone.
130	In the PSN-IRT leaderboard data (12 models $\times$ 5 benchmarks, distinct from our controlled experiments), Mistral ($\text{acc}{=}0.514$, lowest among the 12 models) exhibits $\ell_z^*{=}{+}5.42$ (second highest), because its response pattern follows the IRT-predicted difficulty ordering more closely than higher-accuracy models whose responses violate the assumed item structure.
131	This dissociation explains why Mistral produces the strongest contamination signal despite the lowest accuracy: its lower baseline ability ($\hat{\theta}{=}{-}1.16$) provides greater $\theta$-shift headroom.
132	
133	\section{Leaderboard Aberrance Analysis}
134	\label{app:leaderboard_aberrance}
135	
136	We computed $\ell_z^*$ and accuracy $z$-scores for all 12 models $\times$ 5 benchmarks $=$ 60 cells in the PSN-IRT leaderboard dataset.
137	Using the standard $|\ell_z^*| > 1.96$ threshold ($\alpha{=}0.05$, two-tailed), 57 of 60 cells are flagged as aberrant, indicating pervasive IRT assumption violations in production LLM responses.
138	In contrast, accuracy $z$-scores ($|z| > 1.96$) flag only 4 of 60 cells.
139	This stark asymmetry---95\% aberrance by $\ell_z^*$ versus 7\% by accuracy---motivates the $\Delta\ell_z^*$ matched-difference design (\S\ref{sec:did}), which sidesteps absolute thresholds by comparing each model against its own clean baseline.
140	
141	\section{Item-Level Detection Results}
142	\label{app:item_auroc}
143	
144	Table~\ref{tab:item_auroc} reports item-level contamination detection performance at 15\% contamination on MMLU.
145	All methods perform near random (AUROC $\leq 0.63$), confirming that contamination is diffuse across the response pattern and that model-level aggregation via $\ell_z^*$ is essential.
146	
147	An accuracy $z$-score baseline yields $z{=}160$ at 15\% contamination, but this reflects near-zero cross-seed accuracy variance ($\text{std}{=}0.0003$), not genuine discriminability.
148	In deployment, accuracy variability from prompt format, evaluation harness, and hardware differences inflates the denominator, collapsing the $z$-score.
149	
150	\begin{table}[t]
151	\centering
152	\caption{Item-level contamination detection (AUROC) at 15\% contamination on MMLU.}
153	\label{tab:item_auroc}
154	\footnotesize
155	\begin{tabular}{@{}lc@{}}
156	\toprule
157	Method & AUROC \\
158	\midrule
159	Random baseline & 0.50 \\
160	$\ell_z^*$ itemwise & 0.53 \\
161	LR cross-model & 0.59 \\
162	RF cross-model & 0.63 \\
163	\bottomrule
164	\end{tabular}
165	\end{table}
166	
167	\section{Robustness Analysis}
168	\label{app:robustness}
169	
170	\subsection{$\Delta\ell_z^*$ Under Local Dependence}
171	\label{app:local_dep}
172	
173	IRT person-fit statistics assume local independence---conditional on $\theta$, item responses are independent.
174	LLM benchmarks violate this assumption through topical clustering (e.g., MMLU subjects); resampling-based approaches can provide valid person-fit assessment even under such violations \citep{sinharay2016}.
175	We evaluate whether the $\Delta\ell_z^*$ matched-difference design is robust to local dependence (LD) via two simulation scenarios on 14,042 MMLU items with 1,000 replications each.
176	
177	\paragraph{Shared LD.}
178	Clean and contaminated conditions share identical testlet structure (${\sim}200$ testlets of ${\sim}70$ items, random effect $\gamma_t \sim \mathcal{N}(0, \sigma_\tau)$).
179	Table~\ref{tab:ld_shared} reports absolute $\ell_z^*$ Type~I error and the ratio of $\Delta\ell_z^*$ effect size ($d$) to the no-LD baseline.
180	While absolute $\ell_z^*$ Type~I error inflates severely under LD (0.043$\to$0.939 at $\sigma{=}1.0$), the $\Delta\ell_z^*$ design maintains detection power: $d_{\text{ratio}} \geq 0.93$ for $\sigma_\tau \leq 0.5$ (realistic range), confirming that shared misfit is cancelled by the matched-difference design.
181	
182	\begin{table}[t]
183	\centering
184	\caption{Robustness of $\Delta\ell_z^*$ to shared local dependence (1,000 replications, MMLU). $d_{\text{ratio}}$: effect size relative to the $\sigma_\tau{=}0$ baseline.}
185	\label{tab:ld_shared}
186	\footnotesize
187	\begin{tabular}{@{}lccc@{}}
188	\toprule
189	$\sigma_\tau$ & Abs.\ $\ell_z^*$ Type~I & $d_{\text{ratio}}$ (15\%) & $d_{\text{ratio}}$ (50\%) \\
190	\midrule
191	0.0 & 0.043 & 1.000 & 1.000 \\
192	0.3 & 0.110 & 1.002 & 1.038 \\
193	0.5 & 0.454 & 0.934 & 1.028 \\
194	1.0 & 0.939 & 0.705 & 1.061 \\
195	\bottomrule
196	\end{tabular}
197	\end{table}
198	
199	\paragraph{Asymmetric LD.}
200	In the second scenario, contaminated models' seen items share an additional memory factor ($\gamma_{\text{mem}} \sim \mathcal{N}(0, \sigma_{\text{mem}})$), simulating contamination-specific LD not present in clean conditions ($\sigma_\tau{=}0.5$ fixed).
201	Table~\ref{tab:ld_asym} shows that $\Delta\ell_z^*$ maintains ${\geq}98.5\%$ power across all conditions, even when contamination introduces asymmetric dependence among seen items.
202	
203	\begin{table}[t]
204	\centering
205	\caption{$\Delta\ell_z^*$ detection under asymmetric local dependence ($\sigma_\tau{=}0.5$, contamination-specific memory factor $\sigma_{\text{mem}}$; 1,000 replications, MMLU).}
206	\label{tab:ld_asym}
207	\footnotesize
208	\begin{tabular}{@{}lcccc@{}}
209	\toprule
210	$\sigma_{\text{mem}}$ & Power (15\%) & $d$ (15\%) & Power (50\%) & $d$ (50\%) \\
211	\midrule
212	0.5 & 0.987 & $-$2.107 & 0.991 & $-$2.337 \\
213	1.0 & 0.993 & $-$2.104 & 0.985 & $-$1.587 \\
214	\bottomrule
215	\end{tabular}
216	\end{table}
217	
218	\subsection{Sensitivity to Item Parameter Estimation Error}
219	\label{app:param_perturb}
220	
221	PSN-IRT item parameters carry estimation error from the calibration sample.
222	We evaluate detection sensitivity by adding joint noise to all four parameters: multiplicative perturbation $p' = p \cdot (1 + \mathcal{N}(0, \sigma))$ for $a$, $c$, and $d$; additive perturbation $b' = b + \sigma \cdot \mathcal{N}(0, 1)$ for difficulty.
223	Tables~\ref{tab:param_noise_free} and \ref{tab:param_noise_fixed} report results over 100 trials using Qwen MMLU response vectors.
224	
225	Detection of 15\% contamination is robust to parameter noise under free-$\theta$ (17.4\% bias at $\sigma{=}10\%$, $|d|$ still ${>}5$; Table~\ref{tab:param_noise_free}).
226	The 50\% contamination condition under free-$\theta$ is fragile---consistent with its already-weak signal due to $\theta$-shift absorption (\S\ref{sec:inverted_u}).
227	
228	Under $\theta$-fixed estimation (Table~\ref{tab:param_noise_fixed}), detection is highly robust: 10\% perturbation produces ${<}4\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\% contamination) and $12.20$ (50\%)---both far exceeding conventional thresholds.
229	This contrasts sharply with free-$\theta$ estimation, where 50\% contamination Cohen's $d$ collapses to near zero under 10\% noise.
230	The complementarity is clear: conditions where free-$\theta$ detection is fragile (high-baseline-accuracy models with $\theta$-shift absorption) are precisely where $\theta$-fixed anchoring provides the strongest and most noise-robust signal.
231	
232	\begin{table}[t]
233	\centering
234	\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, free-$\theta$). \% bias relative to noise-free $d$.}
235	\label{tab:param_noise_free}
236	\footnotesize
237	\begin{tabular}{@{}lcccc@{}}
238	\toprule
239	Noise $\sigma$ & $d$ (15\%) & \% bias & $d$ (50\%) & \% bias \\
240	\midrule
241	0\% & $-$6.575 & --- & $-$1.897 & --- \\
242	5\% & $-$6.010 & 8.6 & $-$0.925 & 51.2 \\
243	10\% & $-$5.433 & 17.4 & $-$0.014 & 99.3 \\
244	\bottomrule
245	\end{tabular}
246	\end{table}
247	
248	\begin{table}[t]
249	\centering
250	\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, $\theta$-fixed). Worst-case $|d|$ over 100 trials in parentheses.}
251	\label{tab:param_noise_fixed}
252	\footnotesize
253	\resizebox{\columnwidth}{!}{%
254	\begin{tabular}{@{}lcccc@{}}
255	\toprule
256	Noise $\sigma$ & $d_{\text{fixed}}$ (15\%) & \% bias & $d_{\text{fixed}}$ (50\%) & \% bias \\
257	\midrule
258	0\% & 4.77 & --- & 14.52 & --- \\
259	5\% & 5.07 $\pm$ 0.24 & 6.3 & 14.76 $\pm$ 0.44 & 1.6 \\
260	10\% & 4.95 $\pm$ 0.43 (3.73) & 3.7 & 14.45 $\pm$ 0.85 (12.20) & 0.5 \\
261	\bottomrule
262	\end{tabular}}
263	\end{table}
264	
265	\section{BCa Bootstrap Sensitivity Check}
266	\label{app:bca}
267	
268	As a sensitivity check, we computed bias-corrected and accelerated (BCa) bootstrap confidence intervals for all Cohen's $d$ estimates.
269	BCa CIs were uniformly narrower than the percentile CIs reported in the main text (mean reduction 22\%), confirming that our reported intervals are conservative.
270	The single condition where BCa widens the zero-crossing set---Llama fixed-$\theta$ at 50\% contamination, BCa CI [$-$0.13, 2.21] vs.\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \S\ref{sec:theta_dynamics}.
271	
272	\section{Classical IRT Refit from Leaderboard Data}
273	\label{app:mml_em}
274	
275	To assess whether item parameters can be recovered without PSN-IRT's neural calibration, we applied classical MML-EM estimation (Gauss--Hermite quadrature, $Q{=}31$ nodes) to binary response data from $N{=}178$ models on the Open LLM Leaderboard v1.
276	With 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.
277	
278	Table~\ref{tab:mml_em} reports parameter correlations between MML-EM-fitted and PSN-IRT parameters.
279	Difficulty shows moderate agreement ($r_b{=}0.663$), but discrimination is essentially unrecovered ($r_a{=}0.127$).
280	Using these MML-EM parameters produces miscalibrated $\ell_z^*$ statistics (mean$\,{=}\,$11.2, expected ${\approx}\,$0), confirming that the refitted model does not capture the data-generating process.
281	This motivates the dependence on PSN-IRT's externally calibrated item bank (\S\ref{sec:framework}).
282	
283	\begin{table}[t]
284	\centering
285	\caption{Parameter correlation between classical MML-EM refit ($N{=}178$ models) and PSN-IRT on MMLU ($n{=}10{,}558$ matched items).}
286	\label{tab:mml_em}
287	\footnotesize
288	\begin{tabular}{@{}llcc@{}}
289	\toprule
290	Model & Parameter & Pearson $r$ & Spearman $\rho$ \\
291	\midrule
292	3PL & $a$ (discrim.) & 0.127 & 0.135 \\
293	3PL & $b$ (difficulty) & 0.663 & 0.684 \\
294	2PL & $a$ (discrim.) & $-$0.029 & 0.050 \\
295	2PL & $b$ (difficulty) & 0.608 & 0.656 \\
296	\bottomrule
297	\end{tabular}
298	\end{table}
299	
300	\section{Post-RL Preliminary Observation}
301	\label{app:post_rl}
302	
303	\citet{wang2025fragility} show that all MIA-based detectors fail after RL post-training.
304	In a single-model pilot ($N{=}1$, Qwen, GRPO), we applied GRPO \citep{shao2024} for 1,500 steps to a contaminated model (15\% MMLU) and evaluated at three checkpoints.
305	GRPO erases the accuracy gap between seen and unseen items ($11.4\text{pp} \to 2.1\text{pp}$), but the $\ell_z^*$ response-pattern gap persists (${\sim}3.3$; Figure~\ref{fig:grpo}), suggesting structural traces of contamination may survive RL alignment.
306	Min-K\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\ell_z^*$ detects persists.
307	This $N{=}1$ observation requires validation across model families, RL methods, and contamination levels before any conclusions can be drawn.
308	
309	\begin{figure}[t]
310	  \centering
311	  \includegraphics[width=\columnwidth]{fig_grpo.pdf}
312	  \caption{Post-RL trajectory for Qwen contaminated at 15\% on MMLU. Left axis: accuracy on seen (solid) and unseen (dashed) items. Right axis: $\ell_z^*$ seen-unseen gap (green diamonds). GRPO erases the accuracy gap ($11.4\text{pp} \to 2.1\text{pp}$) while the response-pattern gap persists (${\sim}3.3$). $N{=}1$, single model and RL method; no statistical inference is drawn.}
313	  \label{fig:grpo}
314	\end{figure}
315	
316	\paragraph{GRPO hyperparameters.}
317	Table~\ref{tab:grpo_hyperparams} reports the GRPO training hyperparameters for the post-RL extension (\S\ref{sec:setup}).
318	
319	\begin{table}[t]
320	\centering
321	\caption{GRPO training hyperparameters (Qwen2.5-7B-Instruct, 15\% MMLU contamination).}
322	\label{tab:grpo_hyperparams}
323	\footnotesize
324	\resizebox{\columnwidth}{!}{%
325	\begin{tabular}{@{}ll@{}}
326	\toprule
327	Hyperparameter & Value \\
328	\midrule
329	Learning rate & $5 \times 10^{-6}$ \\
330	Per-device batch size & 2 \\
331	Gradient accumulation steps & 4 \\
332	Num.\ generations per prompt & 16 \\
333	Max completion length & 128 \\
334	Sampling temperature & 1.2 \\
335	Training steps & 1,500 (checkpoints at 500, 1000, 1500) \\
336	Reward function & Correctness-based ($+1.0$ correct, $-1.0$ incorrect) \\
337	LoRA rank / $\alpha$ / dropout & 16 / 32 / 0.05 \\
338	Precision & BF16 \\
339	Seed & 42 \\
340	\bottomrule
341	\end{tabular}}
342	\end{table}
343	
344	\section{QLoRA Training Hyperparameters}
345	\label{app:hyperparams}
346	
347	Table~\ref{tab:hyperparams} reports the QLoRA fine-tuning hyperparameters used across all experiments.
348	
349	\begin{table}[t]
350	\centering
351	\caption{QLoRA fine-tuning hyperparameters (shared across all model families and contamination conditions).}
352	\label{tab:hyperparams}
353	\footnotesize
354	\resizebox{\columnwidth}{!}{%
355	\begin{tabular}{@{}ll@{}}
356	\toprule
357	Hyperparameter & Value \\
358	\midrule
359	Quantization & 4-bit NF4 \\
360	LoRA rank & 16 \\
361	LoRA $\alpha$ & 32 \\
362	LoRA dropout & 0.05 \\
363	Target modules & \texttt{q\_proj}, \texttt{k\_proj}, \texttt{v\_proj}, \texttt{o\_proj} \\
364	Learning rate & $2 \times 10^{-4}$ \\
365	Optimizer & AdamW \\
366	Warmup ratio & 0.1 \\
367	Epochs & 3 \\
368	Per-device batch size & 4 \\
369	Gradient accumulation steps & 4 \\
370	Effective batch size & 16 \\
371	Max sequence length & 512 \\
372	Data mixing & Contaminated items shuffled into training set \\
373	\bottomrule
374	\end{tabular}}
375	\end{table}
376	
377	\section{Contamination Run Reproducibility}\label{app:reproducibility}
378	
379	\begin{table}[h]
380	\centering
381	\caption{Reproducibility of contamination effect sizes across independent QLoRA runs (Qwen2.5-7B-Instruct, MMLU). Each row shows Cohen's $|d|$ from an independent training seed against the shared $n{=}10$ clean baseline ($\bar{\ell}_z^* = 8.68$, $s = 0.74$). All runs use identical hyperparameters; only the random seed differs.}
382	\footnotesize
383	\begin{tabular}{@{}lcccccc@{}}
384	\toprule
385	& \multicolumn{3}{c}{Free-$\theta$ $|d|$} & \multicolumn{3}{c}{Fixed-$\theta$ $|d|$} \\
386	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
387	Seed & 15\% & 25\% & 50\% & 15\% & 25\% & 50\% \\
388	\midrule
389	42 (original) & 6.57 & 8.22 & 1.90 & 4.77 & 4.96 & 14.52 \\
390	123 & 5.09 & 8.78 & 5.42 & 7.79 & 5.37 & 12.64 \\
391	456 & 4.41 & 5.31 & 7.91 & 7.99 & 7.34 & 9.80 \\
392	\addlinespace
393	Mean & 5.36 & 7.44 & 5.08 & 6.85 & 5.89 & 12.32 \\
394	SD & 1.10 & 1.86 & 3.02 & 1.80 & 1.27 & 2.38 \\
395	CV (\%) & 20.3 & 25.2 & 59.6 & 26.3 & 21.7 & 19.3 \\
396	\bottomrule
397	\end{tabular}
398	\vspace{0.5em}
399	
400	\noindent\textit{Note.} Fixed-$\theta$ estimation anchors $\hat{\theta}$ at the clean-baseline mean ($\theta{=}{-}0.102$), removing $\theta$-shift absorption. The 50\% free-$\theta$ column exhibits high CV (59.6\%), reflecting seed-dependent $\theta$-shift magnitude; fixed-$\theta$ reduces this to 19.3\%, confirming that cross-seed variability at high contamination is driven by ability-estimate instability rather than true signal variance.
401	\end{table}
402	
403	\begin{table}[h]
404	\centering
405	\caption{Multi-seed Cohen's $|d|$ for HT and accuracy $z$-score statistics (Qwen2.5-7B-Instruct, MMLU), computed using the chi-squared ratio HT statistic and bootstrap Cohen's $d$ (10{,}000 resamples). These supplement the $\ell_z^*$ values in Table~\ref{tab:degradation}.}
406	\label{tab:ht_acc_multiseed}
407	\footnotesize
408	\begin{tabular}{@{}lcccccc@{}}
409	\toprule
410	& \multicolumn{3}{c}{HT $|d|$} & \multicolumn{3}{c}{Acc.\ $z$ $|d|$} \\
411	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
412	Seed & 15\% & 25\% & 50\% & 15\% & 25\% & 50\% \\
413	\midrule
414	42 (original) & 7.26 & 8.90 & 1.66 & 42.3 & 49.8 & 68.7 \\
415	123 & 5.52 & 9.51 & 5.80 & 47.3 & 53.4 & 70.8 \\
416	456 & 4.72 & 5.10 & 8.41 & 45.4 & 51.3 & 70.4 \\
417	\addlinespace
418	Mean & 5.83 & 7.84 & 5.29 & 45.0 & 51.5 & 70.0 \\
419	SD & 1.30 & 2.39 & 3.41 & 2.5 & 1.8 & 1.1 \\
420	\bottomrule
421	\end{tabular}
422	\vspace{0.5em}
423	
424	\noindent\textit{Note.} HT exhibits high cross-seed variance at 50\% (SD${=}3.41$), mirroring the $\ell_z^*$ pattern: the non-monotonicity observed in seed 42 ($|d|{=}1.66$) does not generalize across seeds. Accuracy $z$-scores are highly stable (CV $< 6\%$) and monotonically increasing with contamination level.
425	\end{table}
426	
427	\begin{table}[h]
428	\centering
429	\caption{Multi-seed Cohen's $d$ for Llama-3.1-8B across all contamination levels (MMLU). Each cell shows Cohen's $d$ from an independent training seed against the shared $n{=}10$ clean baseline ($\bar{\ell}_z^* = {+}0.26$, $s = 1.54$). The 5\% condition exhibits higher cross-seed variance (SD${=}0.99$), reflecting the weaker signal from ${\sim}700$ contaminated items (5\%$\times$14{,}042).}
430	\label{tab:llama_multiseed}
431	\footnotesize
432	\begin{tabular}{@{}lcccccc@{}}
433	\toprule
434	& \multicolumn{3}{c}{Per-seed $d$} & & \\
435	\cmidrule(lr){2-4}
436	Contam.\ level & $s_1$ & $s_2$ & $s_3$ & Mean & SD \\
437	\midrule
438	5\%  & $-$3.22 & $-$3.06 & $-$1.44 & $-$2.57 & 0.99 \\
439	15\% & $-$2.11 & $-$3.21 & $-$3.09 & $-$2.80 & 0.60 \\
440	25\% & $-$3.16 & $-$2.28 & $-$2.24 & $-$2.56 & 0.52 \\
441	50\% & $-$2.33 & $-$2.59 & $-$1.99 & $-$2.30 & 0.30 \\
442	\bottomrule
443	\end{tabular}
444	\vspace{0.5em}
445	
446	\noindent\textit{Note.} Unlike Qwen, Llama exhibits no non-monotonic dose-response: mean $|d|$ is approximately flat across contamination levels ($2.30$--$2.80$), consistent with its near-zero baseline $\ell_z^*$ ($+0.26$) and negligible $\theta$-shift absorption (\S\ref{sec:theta_dynamics}). Cross-seed variance decreases with contamination level (CV: 39\% at 5\% $\to$ 13\% at 50\%), suggesting that higher contamination produces a more stable signal despite the flat mean trajectory.
447	\end{table}
448	
449	\begin{table}[h]
450	\centering
451	\caption{Multi-seed Cohen's $d$ for Mistral-7B-Instruct across contamination levels (MMLU). Each cell shows Cohen's $d$ from an independent training seed against the shared $n{=}10$ clean baseline ($\bar{\ell}_z^* = {+}4.02$, $s = 2.05$).}
452	\label{tab:mistral_multiseed}
453	\footnotesize
454	\begin{tabular}{@{}lcccccc@{}}
455	\toprule
456	& \multicolumn{3}{c}{Per-seed $d$} & & \\
457	\cmidrule(lr){2-4}
458	Contam.\ level & $s_1$ & $s_2$ & $s_3$ & Mean & SD \\
459	\midrule
460	15\% & $-$2.64 & $-$3.98 & $-$3.49 & $-$3.37 & 0.68 \\
461	50\% & $-$3.50 & $-$4.25 & $-$4.51 & $-$4.09 & 0.53 \\
462	\bottomrule
463	\end{tabular}
464	\vspace{0.5em}
465	
466	\noindent\textit{Note.} Mistral exhibits monotonic dose-response: mean $|d|$ increases from 3.37 (15\%) to 4.09 (50\%), consistent with its moderate baseline $\ell_z^*$ ($+4.02$) and lower baseline accuracy (52.4\%), which provides greater $\theta$-shift headroom. Cross-seed variance is modest at both levels (CV: 20\% at 15\%, 13\% at 50\%).
467	\end{table}
468	
469	\paragraph{Item selection seed robustness.}
470	As a pipeline validation, we retrained Llama at 15\% and 50\% contamination using a different item selection seed (seed${=}42$ vs.\ the original seed${=}999$), which selects a distinct subset of MMLU items for contamination.
471	The resulting $\ell_z^*$ values are numerically identical ($-2.992$ vs.\ $-2.992$ at 15\%; $-3.331$ vs.\ $-3.331$ at 50\%), confirming that $\ell_z^*$ is robust to which specific items are contaminated and depends primarily on the contamination proportion.
472	
473	\section{Use of AI Assistants}
474	\label{app:ai-assistants}
475	
476	We used Claude (Anthropic) as an AI coding and writing assistant
477	throughout this work. Specifically:
478	\begin{itemize}
479	    \item \textbf{Code:} drafting experiment scripts, data-processing
480	    pipelines, and analysis utilities; debugging and refactoring.
481	    \item \textbf{Writing:} drafting and revising paper sections,
482	    polishing prose, and reformatting LaTeX.
483	    \item \textbf{Literature:} summarizing related papers to inform
484	    related-work section.
485	\end{itemize}
486	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ca3108bc-cec3-4515-850e-15e6ea950c54",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "24c0eb6d-b7d8-4853-9ae0-b3d88c60c6ac",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex",
      "content": "\\section{Simulation Validation}\n\\label{app:simulation}\n\nUnder the null (no contamination), bootstrap $\\ell_z^*$ tracks $\\mathcal{N}(0,1)$: mean bias 0.041 and standard deviation 1.003 on MMLU.\nKolmogorov--Smirnov rejection rates vary with benchmark size: 8.3\\% for MMLU and HellaSwag ($n > 10{,}000$), 50.0\\% for GSM8K ($n = 1{,}319$), 58.3\\% for ARC-C ($n = 295$), and 75.0\\% for HumanEval ($n = 164$).\n$\\ell_z^*$ is well-calibrated for benchmarks with $n \\geq 10{,}000$ items; smaller benchmarks show increasing finite-sample deviations from normality.\n\nTwo-sided testing eliminates the inverted-U artifact: MMLU achieves 97.8\\% power at 15\\% contamination and sustains ${>}$93\\% at all levels.\nPower scales with $\\sqrt{n}$, as predicted by the noncentrality parameter $\\delta \\propto \\sqrt{n}$.\nThe empirical power function, derived via Gauss--Hermite quadrature ($K=30$) over the ability distribution, achieves $R^2 = 0.957$ against simulated values, with approximate minimum benchmark size of $n \\geq 7{,}958$ items for 80\\% power at 15\\% contamination under MMLU item parameters.\n\n\\section{4PL vs.\\ 3PL Ablation Details}\n\\label{app:4pl_ablation}\n\nTable~\\ref{tab:4pl_3pl_power} reports detection power (proportion of 2{,}000 simulation replicates rejecting $H_0$ at $\\alpha{=}0.05$, two-sided) for 4PL and 3PL parameterizations across five benchmarks and seven contamination levels.\nThe 4PL model yields higher power than 3PL at every non-trivial contamination level on every benchmark.\nThe advantage is largest on MMLU and HellaSwag, where upper-asymptote ($d < 1$) violations are most prevalent, and smallest on ARC-Challenge and HumanEval, where limited item counts constrain power under both parameterizations.\n\nPower is non-monotonic at 75\\% contamination under 4PL on four of five benchmarks (e.g., MMLU: $.952 \\to .938$; GSM8K: $.846 \\to .802$).\nThis reflects the $\\theta$-shift boundary condition described in \\S\\ref{sec:inverted_u}: at high contamination fractions, re-estimated $\\hat{\\theta}$ absorbs part of the aberrance signal, reducing $|\\ell_z^*|$.\nAt 100\\% contamination, all items are seen and power reaches 1.000 trivially.\nThe 4PL advantage over 3PL depends on accurate estimation of the upper asymptote $d$; with estimation error exceeding ${\\sim}10\\%$, the effective model behavior approaches 3PL ($d{=}1$) and the power gain diminishes.\nPSN-IRT's large calibration sample ($12{+}$ models per item) typically yields $d$ standard errors well below this threshold.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Detection power (proportion rejecting $H_0$ at $\\alpha{=}0.05$) under 4PL and 3PL parameterizations across benchmarks and contamination levels ($n{=}2{,}000$ replicates per cell). Bold indicates the 4PL advantage exceeds 5\\,pp.}\n\\label{tab:4pl_3pl_power}\n\\small\n\\begin{tabular}{@{}llccccccc@{}}\n\\toprule\nBenchmark & IRT & 5\\% & 10\\% & 15\\% & 25\\% & 50\\% & 75\\% & 100\\% \\\\\n\\midrule\nMMLU & 4PL & \\textbf{.476} & \\textbf{.848} & \\textbf{.969} & \\textbf{.983} & \\textbf{.952} & \\textbf{.938} & 1.00 \\\\\n     & 3PL & .227 & .340 & .412 & .521 & .676 & .770 & 1.00 \\\\\n\\addlinespace\nHellaSwag & 4PL & \\textbf{.251} & \\textbf{.454} & \\textbf{.656} & \\textbf{.915} & \\textbf{.939} & \\textbf{.919} & 1.00 \\\\\n          & 3PL & .167 & .241 & .313 & .368 & .508 & .642 & 1.00 \\\\\n\\addlinespace\nGSM8K & 4PL & \\textbf{.156} & \\textbf{.309} & \\textbf{.492} & \\textbf{.737} & \\textbf{.846} & \\textbf{.802} & 1.00 \\\\\n      & 3PL & .102 & .172 & .285 & .396 & .567 & .577 & 1.00 \\\\\n\\addlinespace\nARC-C & 4PL & .057 & .075 & .087 & \\textbf{.130} & \\textbf{.285} & \\textbf{.493} & 1.00 \\\\\n      & 3PL & .054 & .062 & .071 & .076 & .110 & .102 & 1.00 \\\\\n\\addlinespace\nHumanEval & 4PL & .076 & .121 & \\textbf{.197} & \\textbf{.302} & \\textbf{.554} & \\textbf{.521} & 1.00 \\\\\n          & 3PL & .063 & .086 & .120 & .182 & .281 & .315 & 1.00 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\section{Seed Sensitivity Analysis}\n\\label{app:seed_sensitivity}\n\n\\paragraph{Clean-baseline variability.}\nTable~\\ref{tab:seed_sensitivity} reports $\\ell_z^*$, accuracy, and $\\hat{\\theta}_{\\text{MLE}}$ across three independent QLoRA runs (seeds 42, 123, 456).\nFor Qwen2.5-7B, $\\ell_z^*$ ranges from $7.05$ (seed 123) to $9.53$ (seed 456); the lower value of seed 123 likely reflects seed-specific training dynamics (random initialization, data ordering), but all three seeds produce $\\ell_z^* \\gg 1.96$, confirming that the elevated baseline reflects systematic model--benchmark misfit rather than seed-specific artifacts.\nLlama-3.1-8B shows $\\ell_z^*$ near zero ($-0.14 \\pm 0.97$), consistent with lower baseline misfit.\nAccuracy variability is negligible for both families (CV $< 0.004$).\n\n\\begin{table}[t]\n\\centering\n\\caption{Seed sensitivity analysis for clean baseline across three independent runs (seeds 42, 123, 456). CV = coefficient of variation ($\\mathrm{std}/|\\mathrm{mean}|$). These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \\S\\ref{sec:detection}; retained for methodological transparency.}\n\\label{tab:seed_sensitivity}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\nModel & Metric & Mean & Std & Range & CV \\\\\n\\midrule\nQwen2.5-7B & $\\ell_z^*$ & 8.684 & 1.412 & 2.475 & 0.163 \\\\\n & Accuracy & 0.679 & 0.000 & 0.001 & 0.001 \\\\\n & $\\hat{\\theta}_{\\mathrm{MLE}}$ & $-$0.097 & 0.012 & 0.023 & 0.119 \\\\\n\\midrule\nLlama-3.1-8B & $\\ell_z^*$ & $-$0.141 & 0.965 & 1.929 & 6.860 \\\\\n & Accuracy & 0.594 & 0.002 & 0.004 & 0.004 \\\\\n & $\\hat{\\theta}_{\\mathrm{MLE}}$ & $-$0.645 & 0.019 & 0.036 & 0.029 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Cohen's $d$ confidence intervals.}\nTable~\\ref{tab:cohens_d_ci} reports Cohen's $d$ effect sizes with both analytic and bootstrap 95\\% confidence intervals.\nAnalytic CIs use $d \\pm t_{0.025,\\,\\text{df}=2} \\cdot \\text{SE}_d$; with only $n{=}3$ clean seeds (df${=}2$), the critical value $t_{0.025,2} = 4.303$ produces intervals wide enough to cross zero in all four conditions.\nThis is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.\nBootstrap CIs (10{,}000 resamples with replacement from the three clean seeds) provide a nonparametric alternative: all four bootstrap intervals exclude zero, supporting the conclusion that contamination produces a reliably detectable signal despite the small reference sample.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cohen's $d$ with 95\\% confidence intervals for contaminated conditions relative to clean baselines ($n{=}3$ seeds). Analytic CIs use $t_{0.025, \\text{df}=2}$; bootstrap CIs use 10{,}000 resamples. These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \\S\\ref{sec:detection}; retained for methodological transparency.}\n\\label{tab:cohens_d_ci}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\nModel & Cond. & $d$ & Analytic CI & Bootstrap CI \\\\\n\\midrule\nQwen & 15\\% & $-$3.42 & [$-$9.92, 3.08] & [$-$3.45, $-$2.82] \\\\\n & 50\\% & $-$0.99 & [$-$4.02, 2.04] & [$-$0.99, $-$0.41] \\\\\n\\midrule\nLlama & 15\\% & $-$2.95 & [$-$8.70, 2.80] & [$-$5.89, $-$2.29] \\\\\n & 50\\% & $-$3.31 & [$-$9.63, 3.01] & [$-$6.47, $-$2.59] \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Cross-family consistency.}\nTable~\\ref{tab:cross_family} confirms that both model families produce large negative Cohen's $d$ under contamination.\nThe $|\\Delta d| = 2.32$ gap at 50\\% contamination reflects Qwen's non-monotonic dose-response (the $\\theta$-shift boundary condition; \\S\\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-family consistency of contamination detection ($n{=}3$ pilot). Both families show large negative $d$ under contamination. Superseded by $n{=}10$ results in \\S\\ref{sec:detection}; retained for methodological transparency.}\n\\label{tab:cross_family}\n\\small\n\\begin{tabular}{@{}lcccl@{}}\n\\toprule\nCondition & Qwen $d$ & Llama $d$ & $|\\Delta d|$ & Consistent? \\\\\n\\midrule\n15\\% contam. & $-$3.42 & $-$2.95 & 0.47 & Yes \\\\\n50\\% contam. & $-$0.99 & $-$3.31 & 2.32 & Yes \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Baseline $\\ell_z^*$ Interpretation}\n\\label{app:baseline_meaning}\n\nThe baseline $\\ell_z^*$ value reflects a model's difficulty-ordering consistency under the 4PL model, not its accuracy alone.\nIn the PSN-IRT leaderboard data (12 models $\\times$ 5 benchmarks, distinct from our controlled experiments), Mistral ($\\text{acc}{=}0.514$, lowest among the 12 models) exhibits $\\ell_z^*{=}{+}5.42$ (second highest), because its response pattern follows the IRT-predicted difficulty ordering more closely than higher-accuracy models whose responses violate the assumed item structure.\nThis dissociation explains why Mistral produces the strongest contamination signal despite the lowest accuracy: its lower baseline ability ($\\hat{\\theta}{=}{-}1.16$) provides greater $\\theta$-shift headroom.\n\n\\section{Leaderboard Aberrance Analysis}\n\\label{app:leaderboard_aberrance}\n\nWe computed $\\ell_z^*$ and accuracy $z$-scores for all 12 models $\\times$ 5 benchmarks $=$ 60 cells in the PSN-IRT leaderboard dataset.\nUsing the standard $|\\ell_z^*| > 1.96$ threshold ($\\alpha{=}0.05$, two-tailed), 57 of 60 cells are flagged as aberrant, indicating pervasive IRT assumption violations in production LLM responses.\nIn contrast, accuracy $z$-scores ($|z| > 1.96$) flag only 4 of 60 cells.\nThis stark asymmetry---95\\% aberrance by $\\ell_z^*$ versus 7\\% by accuracy---motivates the $\\Delta\\ell_z^*$ matched-difference design (\\S\\ref{sec:did}), which sidesteps absolute thresholds by comparing each model against its own clean baseline.\n\n\\section{Item-Level Detection Results}\n\\label{app:item_auroc}\n\nTable~\\ref{tab:item_auroc} reports item-level contamination detection performance at 15\\% contamination on MMLU.\nAll methods perform near random (AUROC $\\leq 0.63$), confirming that contamination is diffuse across the response pattern and that model-level aggregation via $\\ell_z^*$ is essential.\n\nAn accuracy $z$-score baseline yields $z{=}160$ at 15\\% contamination, but this reflects near-zero cross-seed accuracy variance ($\\text{std}{=}0.0003$), not genuine discriminability.\nIn deployment, accuracy variability from prompt format, evaluation harness, and hardware differences inflates the denominator, collapsing the $z$-score.\n\n\\begin{table}[t]\n\\centering\n\\caption{Item-level contamination detection (AUROC) at 15\\% contamination on MMLU.}\n\\label{tab:item_auroc}\n\\footnotesize\n\\begin{tabular}{@{}lc@{}}\n\\toprule\nMethod & AUROC \\\\\n\\midrule\nRandom baseline & 0.50 \\\\\n$\\ell_z^*$ itemwise & 0.53 \\\\\nLR cross-model & 0.59 \\\\\nRF cross-model & 0.63 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Robustness Analysis}\n\\label{app:robustness}\n\n\\subsection{$\\Delta\\ell_z^*$ Under Local Dependence}\n\\label{app:local_dep}\n\nIRT person-fit statistics assume local independence---conditional on $\\theta$, item responses are independent.\nLLM benchmarks violate this assumption through topical clustering (e.g., MMLU subjects); resampling-based approaches can provide valid person-fit assessment even under such violations \\citep{sinharay2016}.\nWe evaluate whether the $\\Delta\\ell_z^*$ matched-difference design is robust to local dependence (LD) via two simulation scenarios on 14,042 MMLU items with 1,000 replications each.\n\n\\paragraph{Shared LD.}\nClean and contaminated conditions share identical testlet structure (${\\sim}200$ testlets of ${\\sim}70$ items, random effect $\\gamma_t \\sim \\mathcal{N}(0, \\sigma_\\tau)$).\nTable~\\ref{tab:ld_shared} reports absolute $\\ell_z^*$ Type~I error and the ratio of $\\Delta\\ell_z^*$ effect size ($d$) to the no-LD baseline.\nWhile absolute $\\ell_z^*$ Type~I error inflates severely under LD (0.043$\\to$0.939 at $\\sigma{=}1.0$), the $\\Delta\\ell_z^*$ design maintains detection power: $d_{\\text{ratio}} \\geq 0.93$ for $\\sigma_\\tau \\leq 0.5$ (realistic range), confirming that shared misfit is cancelled by the matched-difference design.\n\n\\begin{table}[t]\n\\centering\n\\caption{Robustness of $\\Delta\\ell_z^*$ to shared local dependence (1,000 replications, MMLU). $d_{\\text{ratio}}$: effect size relative to the $\\sigma_\\tau{=}0$ baseline.}\n\\label{tab:ld_shared}\n\\footnotesize\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n$\\sigma_\\tau$ & Abs.\\ $\\ell_z^*$ Type~I & $d_{\\text{ratio}}$ (15\\%) & $d_{\\text{ratio}}$ (50\\%) \\\\\n\\midrule\n0.0 & 0.043 & 1.000 & 1.000 \\\\\n0.3 & 0.110 & 1.002 & 1.038 \\\\\n0.5 & 0.454 & 0.934 & 1.028 \\\\\n1.0 & 0.939 & 0.705 & 1.061 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Asymmetric LD.}\nIn the second scenario, contaminated models' seen items share an additional memory factor ($\\gamma_{\\text{mem}} \\sim \\mathcal{N}(0, \\sigma_{\\text{mem}})$), simulating contamination-specific LD not present in clean conditions ($\\sigma_\\tau{=}0.5$ fixed).\nTable~\\ref{tab:ld_asym} shows that $\\Delta\\ell_z^*$ maintains ${\\geq}98.5\\%$ power across all conditions, even when contamination introduces asymmetric dependence among seen items.\n\n\\begin{table}[t]\n\\centering\n\\caption{$\\Delta\\ell_z^*$ detection under asymmetric local dependence ($\\sigma_\\tau{=}0.5$, contamination-specific memory factor $\\sigma_{\\text{mem}}$; 1,000 replications, MMLU).}\n\\label{tab:ld_asym}\n\\footnotesize\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$\\sigma_{\\text{mem}}$ & Power (15\\%) & $d$ (15\\%) & Power (50\\%) & $d$ (50\\%) \\\\\n\\midrule\n0.5 & 0.987 & $-$2.107 & 0.991 & $-$2.337 \\\\\n1.0 & 0.993 & $-$2.104 & 0.985 & $-$1.587 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Sensitivity to Item Parameter Estimation Error}\n\\label{app:param_perturb}\n\nPSN-IRT item parameters carry estimation error from the calibration sample.\nWe evaluate detection sensitivity by adding joint noise to all four parameters: multiplicative perturbation $p' = p \\cdot (1 + \\mathcal{N}(0, \\sigma))$ for $a$, $c$, and $d$; additive perturbation $b' = b + \\sigma \\cdot \\mathcal{N}(0, 1)$ for difficulty.\nTables~\\ref{tab:param_noise_free} and \\ref{tab:param_noise_fixed} report results over 100 trials using Qwen MMLU response vectors.\n\nDetection of 15\\% contamination is robust to parameter noise under free-$\\theta$ (17.4\\% bias at $\\sigma{=}10\\%$, $|d|$ still ${>}5$; Table~\\ref{tab:param_noise_free}).\nThe 50\\% contamination condition under free-$\\theta$ is fragile---consistent with its already-weak signal due to $\\theta$-shift absorption (\\S\\ref{sec:inverted_u}).\n\nUnder $\\theta$-fixed estimation (Table~\\ref{tab:param_noise_fixed}), detection is highly robust: 10\\% perturbation produces ${<}4\\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\\% contamination) and $12.20$ (50\\%)---both far exceeding conventional thresholds.\nThis contrasts sharply with free-$\\theta$ estimation, where 50\\% contamination Cohen's $d$ collapses to near zero under 10\\% noise.\nThe complementarity is clear: conditions where free-$\\theta$ detection is fragile (high-baseline-accuracy models with $\\theta$-shift absorption) are precisely where $\\theta$-fixed anchoring provides the strongest and most noise-robust signal.\n\n\\begin{table}[t]\n\\centering\n\\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, free-$\\theta$). \\% bias relative to noise-free $d$.}\n\\label{tab:param_noise_free}\n\\footnotesize\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nNoise $\\sigma$ & $d$ (15\\%) & \\% bias & $d$ (50\\%) & \\% bias \\\\\n\\midrule\n0\\% & $-$6.575 & --- & $-$1.897 & --- \\\\\n5\\% & $-$6.010 & 8.6 & $-$0.925 & 51.2 \\\\\n10\\% & $-$5.433 & 17.4 & $-$0.014 & 99.3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, $\\theta$-fixed). Worst-case $|d|$ over 100 trials in parentheses.}\n\\label{tab:param_noise_fixed}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nNoise $\\sigma$ & $d_{\\text{fixed}}$ (15\\%) & \\% bias & $d_{\\text{fixed}}$ (50\\%) & \\% bias \\\\\n\\midrule\n0\\% & 4.77 & --- & 14.52 & --- \\\\\n5\\% & 5.07 $\\pm$ 0.24 & 6.3 & 14.76 $\\pm$ 0.44 & 1.6 \\\\\n10\\% & 4.95 $\\pm$ 0.43 (3.73) & 3.7 & 14.45 $\\pm$ 0.85 (12.20) & 0.5 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{BCa Bootstrap Sensitivity Check}\n\\label{app:bca}\n\nAs a sensitivity check, we computed bias-corrected and accelerated (BCa) bootstrap confidence intervals for all Cohen's $d$ estimates.\nBCa CIs were uniformly narrower than the percentile CIs reported in the main text (mean reduction 22\\%), confirming that our reported intervals are conservative.\nThe single condition where BCa widens the zero-crossing set---Llama fixed-$\\theta$ at 50\\% contamination, BCa CI [$-$0.13, 2.21] vs.\\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \\S\\ref{sec:theta_dynamics}.\n\n\\section{Classical IRT Refit from Leaderboard Data}\n\\label{app:mml_em}\n\nTo assess whether item parameters can be recovered without PSN-IRT's neural calibration, we applied classical MML-EM estimation (Gauss--Hermite quadrature, $Q{=}31$ nodes) to binary response data from $N{=}178$ models on the Open LLM Leaderboard v1.\nWith 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.\n\nTable~\\ref{tab:mml_em} reports parameter correlations between MML-EM-fitted and PSN-IRT parameters.\nDifficulty shows moderate agreement ($r_b{=}0.663$), but discrimination is essentially unrecovered ($r_a{=}0.127$).\nUsing these MML-EM parameters produces miscalibrated $\\ell_z^*$ statistics (mean$\\,{=}\\,$11.2, expected ${\\approx}\\,$0), confirming that the refitted model does not capture the data-generating process.\nThis motivates the dependence on PSN-IRT's externally calibrated item bank (\\S\\ref{sec:framework}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Parameter correlation between classical MML-EM refit ($N{=}178$ models) and PSN-IRT on MMLU ($n{=}10{,}558$ matched items).}\n\\label{tab:mml_em}\n\\footnotesize\n\\begin{tabular}{@{}llcc@{}}\n\\toprule\nModel & Parameter & Pearson $r$ & Spearman $\\rho$ \\\\\n\\midrule\n3PL & $a$ (discrim.) & 0.127 & 0.135 \\\\\n3PL & $b$ (difficulty) & 0.663 & 0.684 \\\\\n2PL & $a$ (discrim.) & $-$0.029 & 0.050 \\\\\n2PL & $b$ (difficulty) & 0.608 & 0.656 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Post-RL Preliminary Observation}\n\\label{app:post_rl}\n\n\\citet{wang2025fragility} show that all MIA-based detectors fail after RL post-training.\nIn a single-model pilot ($N{=}1$, Qwen, GRPO), we applied GRPO \\citep{shao2024} for 1,500 steps to a contaminated model (15\\% MMLU) and evaluated at three checkpoints.\nGRPO erases the accuracy gap between seen and unseen items ($11.4\\text{pp} \\to 2.1\\text{pp}$), but the $\\ell_z^*$ response-pattern gap persists (${\\sim}3.3$; Figure~\\ref{fig:grpo}), suggesting structural traces of contamination may survive RL alignment.\nMin-K\\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\\ell_z^*$ detects persists.\nThis $N{=}1$ observation requires validation across model families, RL methods, and contamination levels before any conclusions can be drawn.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_grpo.pdf}\n  \\caption{Post-RL trajectory for Qwen contaminated at 15\\% on MMLU. Left axis: accuracy on seen (solid) and unseen (dashed) items. Right axis: $\\ell_z^*$ seen-unseen gap (green diamonds). GRPO erases the accuracy gap ($11.4\\text{pp} \\to 2.1\\text{pp}$) while the response-pattern gap persists (${\\sim}3.3$). $N{=}1$, single model and RL method; no statistical inference is drawn.}\n  \\label{fig:grpo}\n\\end{figure}\n\n\\paragraph{GRPO hyperparameters.}\nTable~\\ref{tab:grpo_hyperparams} reports the GRPO training hyperparameters for the post-RL extension (\\S\\ref{sec:setup}).\n\n\\begin{table}[t]\n\\centering\n\\caption{GRPO training hyperparameters (Qwen2.5-7B-Instruct, 15\\% MMLU contamination).}\n\\label{tab:grpo_hyperparams}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ll@{}}\n\\toprule\nHyperparameter & Value \\\\\n\\midrule\nLearning rate & $5 \\times 10^{-6}$ \\\\\nPer-device batch size & 2 \\\\\nGradient accumulation steps & 4 \\\\\nNum.\\ generations per prompt & 16 \\\\\nMax completion length & 128 \\\\\nSampling temperature & 1.2 \\\\\nTraining steps & 1,500 (checkpoints at 500, 1000, 1500) \\\\\nReward function & Correctness-based ($+1.0$ correct, $-1.0$ incorrect) \\\\\nLoRA rank / $\\alpha$ / dropout & 16 / 32 / 0.05 \\\\\nPrecision & BF16 \\\\\nSeed & 42 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{QLoRA Training Hyperparameters}\n\\label{app:hyperparams}\n\nTable~\\ref{tab:hyperparams} reports the QLoRA fine-tuning hyperparameters used across all experiments.\n\n\\begin{table}[t]\n\\centering\n\\caption{QLoRA fine-tuning hyperparameters (shared across all model families and contamination conditions).}\n\\label{tab:hyperparams}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ll@{}}\n\\toprule\nHyperparameter & Value \\\\\n\\midrule\nQuantization & 4-bit NF4 \\\\\nLoRA rank & 16 \\\\\nLoRA $\\alpha$ & 32 \\\\\nLoRA dropout & 0.05 \\\\\nTarget modules & \\texttt{q\\_proj}, \\texttt{k\\_proj}, \\texttt{v\\_proj}, \\texttt{o\\_proj} \\\\\nLearning rate & $2 \\times 10^{-4}$ \\\\\nOptimizer & AdamW \\\\\nWarmup ratio & 0.1 \\\\\nEpochs & 3 \\\\\nPer-device batch size & 4 \\\\\nGradient accumulation steps & 4 \\\\\nEffective batch size & 16 \\\\\nMax sequence length & 512 \\\\\nData mixing & Contaminated items shuffled into training set \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{Contamination Run Reproducibility}\\label{app:reproducibility}\n\n\\begin{table}[h]\n\\centering\n\\caption{Reproducibility of contamination effect sizes across independent QLoRA runs (Qwen2.5-7B-Instruct, MMLU). Each row shows Cohen's $|d|$ from an independent training seed against the shared $n{=}10$ clean baseline ($\\bar{\\ell}_z^* = 8.68$, $s = 0.74$). All runs use identical hyperparameters; only the random seed differs.}\n\\footnotesize\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\n& \\multicolumn{3}{c}{Free-$\\theta$ $|d|$} & \\multicolumn{3}{c}{Fixed-$\\theta$ $|d|$} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSeed & 15\\% & 25\\% & 50\\% & 15\\% & 25\\% & 50\\% \\\\\n\\midrule\n42 (original) & 6.57 & 8.22 & 1.90 & 4.77 & 4.96 & 14.52 \\\\\n123 & 5.09 & 8.78 & 5.42 & 7.79 & 5.37 & 12.64 \\\\\n456 & 4.41 & 5.31 & 7.91 & 7.99 & 7.34 & 9.80 \\\\\n\\addlinespace\nMean & 5.36 & 7.44 & 5.08 & 6.85 & 5.89 & 12.32 \\\\\nSD & 1.10 & 1.86 & 3.02 & 1.80 & 1.27 & 2.38 \\\\\nCV (\\%) & 20.3 & 25.2 & 59.6 & 26.3 & 21.7 & 19.3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{0.5em}\n\n\\noindent\\textit{Note.} Fixed-$\\theta$ estimation anchors $\\hat{\\theta}$ at the clean-baseline mean ($\\theta{=}{-}0.102$), removing $\\theta$-shift absorption. The 50\\% free-$\\theta$ column exhibits high CV (59.6\\%), reflecting seed-dependent $\\theta$-shift magnitude; fixed-$\\theta$ reduces this to 19.3\\%, confirming that cross-seed variability at high contamination is driven by ability-estimate instability rather than true signal variance.\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Multi-seed Cohen's $|d|$ for HT and accuracy $z$-score statistics (Qwen2.5-7B-Instruct, MMLU), computed using the chi-squared ratio HT statistic and bootstrap Cohen's $d$ (10{,}000 resamples). These supplement the $\\ell_z^*$ values in Table~\\ref{tab:degradation}.}\n\\label{tab:ht_acc_multiseed}\n\\footnotesize\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\n& \\multicolumn{3}{c}{HT $|d|$} & \\multicolumn{3}{c}{Acc.\\ $z$ $|d|$} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSeed & 15\\% & 25\\% & 50\\% & 15\\% & 25\\% & 50\\% \\\\\n\\midrule\n42 (original) & 7.26 & 8.90 & 1.66 & 42.3 & 49.8 & 68.7 \\\\\n123 & 5.52 & 9.51 & 5.80 & 47.3 & 53.4 & 70.8 \\\\\n456 & 4.72 & 5.10 & 8.41 & 45.4 & 51.3 & 70.4 \\\\\n\\addlinespace\nMean & 5.83 & 7.84 & 5.29 & 45.0 & 51.5 & 70.0 \\\\\nSD & 1.30 & 2.39 & 3.41 & 2.5 & 1.8 & 1.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{0.5em}\n\n\\noindent\\textit{Note.} HT exhibits high cross-seed variance at 50\\% (SD${=}3.41$), mirroring the $\\ell_z^*$ pattern: the non-monotonicity observed in seed 42 ($|d|{=}1.66$) does not generalize across seeds. Accuracy $z$-scores are highly stable (CV $< 6\\%$) and monotonically increasing with contamination level.\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Multi-seed Cohen's $d$ for Llama-3.1-8B across all contamination levels (MMLU). Each cell shows Cohen's $d$ from an independent training seed against the shared $n{=}10$ clean baseline ($\\bar{\\ell}_z^* = {+}0.26$, $s = 1.54$). The 5\\% condition exhibits higher cross-seed variance (SD${=}0.99$), reflecting the weaker signal from ${\\sim}700$ contaminated items (5\\%$\\times$14{,}042).}\n\\label{tab:llama_multiseed}\n\\footnotesize\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\n& \\multicolumn{3}{c}{Per-seed $d$} & & \\\\\n\\cmidrule(lr){2-4}\nContam.\\ level & $s_1$ & $s_2$ & $s_3$ & Mean & SD \\\\\n\\midrule\n5\\%  & $-$3.22 & $-$3.06 & $-$1.44 & $-$2.57 & 0.99 \\\\\n15\\% & $-$2.11 & $-$3.21 & $-$3.09 & $-$2.80 & 0.60 \\\\\n25\\% & $-$3.16 & $-$2.28 & $-$2.24 & $-$2.56 & 0.52 \\\\\n50\\% & $-$2.33 & $-$2.59 & $-$1.99 & $-$2.30 & 0.30 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{0.5em}\n\n\\noindent\\textit{Note.} Unlike Qwen, Llama exhibits no non-monotonic dose-response: mean $|d|$ is approximately flat across contamination levels ($2.30$--$2.80$), consistent with its near-zero baseline $\\ell_z^*$ ($+0.26$) and negligible $\\theta$-shift absorption (\\S\\ref{sec:theta_dynamics}). Cross-seed variance decreases with contamination level (CV: 39\\% at 5\\% $\\to$ 13\\% at 50\\%), suggesting that higher contamination produces a more stable signal despite the flat mean trajectory.\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Multi-seed Cohen's $d$ for Mistral-7B-Instruct across contamination levels (MMLU). Each cell shows Cohen's $d$ from an independent training seed against the shared $n{=}10$ clean baseline ($\\bar{\\ell}_z^* = {+}4.02$, $s = 2.05$).}\n\\label{tab:mistral_multiseed}\n\\footnotesize\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\n& \\multicolumn{3}{c}{Per-seed $d$} & & \\\\\n\\cmidrule(lr){2-4}\nContam.\\ level & $s_1$ & $s_2$ & $s_3$ & Mean & SD \\\\\n\\midrule\n15\\% & $-$2.64 & $-$3.98 & $-$3.49 & $-$3.37 & 0.68 \\\\\n50\\% & $-$3.50 & $-$4.25 & $-$4.51 & $-$4.09 & 0.53 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{0.5em}\n\n\\noindent\\textit{Note.} Mistral exhibits monotonic dose-response: mean $|d|$ increases from 3.37 (15\\%) to 4.09 (50\\%), consistent with its moderate baseline $\\ell_z^*$ ($+4.02$) and lower baseline accuracy (52.4\\%), which provides greater $\\theta$-shift headroom. Cross-seed variance is modest at both levels (CV: 20\\% at 15\\%, 13\\% at 50\\%).\n\\end{table}\n\n\\paragraph{Item selection seed robustness.}\nAs a pipeline validation, we retrained Llama at 15\\% and 50\\% contamination using a different item selection seed (seed${=}42$ vs.\\ the original seed${=}999$), which selects a distinct subset of MMLU items for contamination.\nThe resulting $\\ell_z^*$ values are numerically identical ($-2.992$ vs.\\ $-2.992$ at 15\\%; $-3.331$ vs.\\ $-3.331$ at 50\\%), confirming that $\\ell_z^*$ is robust to which specific items are contaminated and depends primarily on the contamination proportion.\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    related-work section.\n\\end{itemize}\n",
      "numLines": 486,
      "startLine": 1,
      "totalLines": 486
    }
  },
  "sourceToolAssistantUUID": "ca3108bc-cec3-4515-850e-15e6ea950c54",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 44 · 2026-05-24T12:17:20.113Z_

```json
{
  "parentUuid": "24c0eb6d-b7d8-4853-9ae0-b3d88c60c6ac",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "f214e56a-59c1-4453-9668-352fc1701336",
  "timestamp": "2026-05-24T12:17:20.113Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 45_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper  Phase 1 确定性检查结果： 源码检查: passed=False, 1 critical, 1 warning 一致性检查:…",
  "leafUuid": "f214e56a-59c1-4453-9668-352fc1701336",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 46_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Assistant

_source line 47 · 2026-05-24T12:17:27.671Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to also read a few more files that might exist. Let me also check for experiments.tex, background.tex, and other section files that are included from main.tex. Looking at main.tex, the included files are:
- sections/abstract
- sections/introduction
- sections/related_work
- sections/method
- sections/results
- sections/discussion
- sections/conclusion
- sections/limitations
- sections/appendix

I've already read all of these. Now let me also do the grep scans for AI style patterns and other checks.

Let me now do the comprehensive audit. Let me first do the regex-based scans for em-dashes, AI filler words, etc.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f214e56a-59c1-4453-9668-352fc1701336",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "a722032f-529d-4fb6-93a5-7a15d56efae6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 48 · 2026-05-24T12:17:28.691Z_

所有 section 文件已读取。现在并行执行正则扫描。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a722032f-529d-4fb6-93a5-7a15d56efae6",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "ce2e0e40-5ecc-497b-bbd1-46eef291d44f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 49 · 2026-05-24T12:17:31.105Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01MbNRgLSLtxF63vHAHnNqch`</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ce2e0e40-5ecc-497b-bbd1-46eef291d44f",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "f268e7e5-da3a-43d7-a513-f18dcc080cdd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 50 · 2026-05-24T12:17:38.528Z_

<details><summary>↩ Tool result · `toolu_014hgfakKFfi9HWNRhvcNybH`</summary>

```text
95 /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "84c53f3f-7d5f-4025-b603-6bbd45b6098d",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "3945d5f4-2faf-438f-a36b-43a2fd8a8b06",
  "toolUseResult": {
    "stdout": "95 /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "84c53f3f-7d5f-4025-b603-6bbd45b6098d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 51 · 2026-05-24T12:17:31.126Z_

<details><summary>↩ Tool result · `toolu_01MbNRgLSLtxF63vHAHnNqch`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f268e7e5-da3a-43d7-a513-f18dcc080cdd",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "85e5a256-27d8-4660-8c90-4620a7a71ea9",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "f268e7e5-da3a-43d7-a513-f18dcc080cdd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-24T12:17:32.079Z_

<details open><summary>🔧 Tool call — Grep · `toolu_015VrwBparCEG8L7cZ6pWxt3`</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "85e5a256-27d8-4660-8c90-4620a7a71ea9",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "1c678af6-da0c-4169-9ae0-01b782e9fa5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 53 · 2026-05-24T12:17:32.096Z_

<details><summary>↩ Tool result · `toolu_015VrwBparCEG8L7cZ6pWxt3`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1c678af6-da0c-4169-9ae0-01b782e9fa5a",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "7e8a0400-3056-44c6-bc59-a2ef3b7de151",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "1c678af6-da0c-4169-9ae0-01b782e9fa5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-24T12:17:33.509Z_

<details open><summary>🔧 Tool call — Grep · `toolu_013FHrdjpVdmo6kdLiYWGGwK`</summary>

```json
{
  "pattern": "(?i)(it is worth noting|notably|importantly|it should be noted|it is important to note)",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7e8a0400-3056-44c6-bc59-a2ef3b7de151",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "05a2cc61-1d30-4a93-8874-9a065733c917",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 55 · 2026-05-24T12:17:33.525Z_

<details><summary>↩ Tool result · `toolu_013FHrdjpVdmo6kdLiYWGGwK`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "05a2cc61-1d30-4a93-8874-9a065733c917",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "186c82cd-440f-4c86-b517-cfd1f831d572",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "05a2cc61-1d30-4a93-8874-9a065733c917",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 56 · 2026-05-24T12:17:34.896Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01NsDJfMPCrYDjtEY6EDoZMr`</summary>

```json
{
  "pattern": "(?i)(delve|leverage|utilize|facilitate|a myriad|a plethora|in the realm of|paradigm shift)",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "186c82cd-440f-4c86-b517-cfd1f831d572",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "1193c2c9-0b06-4aeb-b3b9-498240401847",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 57 · 2026-05-24T12:17:34.915Z_

<details><summary>↩ Tool result · `toolu_01NsDJfMPCrYDjtEY6EDoZMr`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1193c2c9-0b06-4aeb-b3b9-498240401847",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "0793ece5-e452-4726-9a90-f95ca6e273d2",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "1193c2c9-0b06-4aeb-b3b9-498240401847",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 58 · 2026-05-24T12:17:35.882Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01MaZRYaoZAmahMmuMR9U3Ht`</summary>

```json
{
  "pattern": "ing,",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0793ece5-e452-4726-9a90-f95ca6e273d2",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "26f037b5-fb4a-4ee8-8296-0ae2093b8f89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 59 · 2026-05-24T12:17:35.900Z_

<details><summary>↩ Tool result · `toolu_01MaZRYaoZAmahMmuMR9U3Ht`</summary>

```text
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex:4:For practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \emph{which} items drive aberrance rather than merely flagging contamination.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex:8:These diagnostics are invisible to accuracy $z$-scores or HT; our contribution lies in quantifying these theoretically predictable effects in the LLM setting, where magnitudes and boundary conditions are not derivable from theory alone.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex:3:Our controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_setup.tex:4:We evaluate on five benchmarks that span knowledge, reasoning, and code generation: MMLU \citep{hendrycks2021mmlu} (14,042 items), HellaSwag \citep{zellers2019hellaswag} (10,042), GSM8K \citep{cobbe2021gsm8k} (1,319), ARC-Challenge \citep{clark2018arc} (295), and HumanEval \citep{chen2021humaneval} (164).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "26f037b5-fb4a-4ee8-8296-0ae2093b8f89",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "4bdee908-d01f-487b-8581-bcf29e0d521b",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex:4:For practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \\emph{which} items drive aberrance rather than merely flagging contamination.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex:8:These diagnostics are invisible to accuracy $z$-scores or HT; our contribution lies in quantifying these theoretically predictable effects in the LLM setting, where magnitudes and boundary conditions are not derivable from theory alone.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex:3:Our controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_setup.tex:4:We evaluate on five benchmarks that span knowledge, reasoning, and code generation: MMLU \\citep{hendrycks2021mmlu} (14,042 items), HellaSwag \\citep{zellers2019hellaswag} (10,042), GSM8K \\citep{cobbe2021gsm8k} (1,319), ARC-Challenge \\citep{clark2018arc} (295), and HumanEval \\citep{chen2021humaneval} (164).",
    "numLines": 4
  },
  "sourceToolAssistantUUID": "26f037b5-fb4a-4ee8-8296-0ae2093b8f89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 60 · 2026-05-24T12:17:36.833Z_

<details open><summary>🔧 Tool call — Grep · `toolu_015vbU9W5xVsHPMvR3PKVyCS`</summary>

```json
{
  "pattern": "(?i)(furthermore|moreover|additionally)",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4bdee908-d01f-487b-8581-bcf29e0d521b",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "d67b2779-6db9-4141-8aa9-2aad98dba408",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 61 · 2026-05-24T12:17:36.849Z_

<details><summary>↩ Tool result · `toolu_015vbU9W5xVsHPMvR3PKVyCS`</summary>

```text
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex:52:Reported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\%/25\%/50\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\ref{app:reproducibility}).
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex:2:We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination, requiring only binary response patterns and externally calibrated 4PL item parameters; diagnostic $\theta$-anchoring additionally requires a clean baseline.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex:13:No existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d67b2779-6db9-4141-8aa9-2aad98dba408",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "8b7d495f-7f6d-46dc-9832-482cba6f1c19",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex:52:Reported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\\%/25\\%/50\\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\\ref{app:reproducibility}).\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex:2:We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination, requiring only binary response patterns and externally calibrated 4PL item parameters; diagnostic $\\theta$-anchoring additionally requires a clean baseline.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex:13:No existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.",
    "numLines": 3
  },
  "sourceToolAssistantUUID": "d67b2779-6db9-4141-8aa9-2aad98dba408",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 62 · 2026-05-24T12:17:37.778Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01MXz1pSqeFVVxQsSL6WN9Rj`</summary>

```json
{
  "command": "wc -w /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex",
  "description": "Count abstract word count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8b7d495f-7f6d-46dc-9832-482cba6f1c19",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "4c07716c-16eb-49e1-b955-40a502322506",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 63 · 2026-05-24T12:17:37.920Z_

<details><summary>↩ Tool result · `toolu_01MXz1pSqeFVVxQsSL6WN9Rj`</summary>

```text
198 /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4c07716c-16eb-49e1-b955-40a502322506",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "4a1331a8-9515-4440-a8a0-7e626b6835d5",
  "toolUseResult": {
    "stdout": "198 /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "4c07716c-16eb-49e1-b955-40a502322506",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 64 · 2026-05-24T12:17:38.482Z_

<details open><summary>🔧 Tool call — Bash · `toolu_014hgfakKFfi9HWNRhvcNybH`</summary>

```json
{
  "command": "wc -w /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex",
  "description": "Count limitations word count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4a1331a8-9515-4440-a8a0-7e626b6835d5",
  "isSidechain": false,
  "requestId": "req_011CbMNxE4rWq2DwVGL59mDq",
  "type": "assistant",
  "uuid": "84c53f3f-7d5f-4025-b603-6bbd45b6098d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01784k1WZKLyRba5bomdAtTY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26324,
      "cache_read_input_tokens": 52928,
      "output_tokens": 1102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26324,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1102,
          "cache_read_input_tokens": 52928,
          "cache_creation_input_tokens": 26324,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26324
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

_source line 65 · 2026-05-24T12:17:41.044Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me also check for the `---` pattern which is LaTeX em-dash and for en-dash patterns.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3945d5f4-2faf-438f-a36b-43a2fd8a8b06",
  "isSidechain": false,
  "requestId": "req_011CbMNyaookeASdNvteWMiv",
  "type": "assistant",
  "uuid": "b4fbb261-a896-42b1-a537-c4e0dfa849fd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C1jUMHqanKz2zfD4Bi62MS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2157,
      "cache_read_input_tokens": 79252,
      "output_tokens": 527,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 527,
          "cache_read_input_tokens": 79252,
          "cache_creation_input_tokens": 2157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2157
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

_source line 66 · 2026-05-24T12:17:41.650Z_

再做几项补充检查。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b4fbb261-a896-42b1-a537-c4e0dfa849fd",
  "isSidechain": false,
  "requestId": "req_011CbMNyaookeASdNvteWMiv",
  "type": "assistant",
  "uuid": "4478d5d4-a507-4b33-a0ef-c19e6c90af65",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C1jUMHqanKz2zfD4Bi62MS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2157,
      "cache_read_input_tokens": 79252,
      "output_tokens": 527,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 527,
          "cache_read_input_tokens": 79252,
          "cache_creation_input_tokens": 2157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2157
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

_source line 67 · 2026-05-24T12:17:43.019Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01HEjqsHipGeseHPfdkScHyQ`</summary>

```json
{
  "pattern": "---",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4478d5d4-a507-4b33-a0ef-c19e6c90af65",
  "isSidechain": false,
  "requestId": "req_011CbMNyaookeASdNvteWMiv",
  "type": "assistant",
  "uuid": "5ce7d777-35bb-4877-88a3-c22a55040242",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C1jUMHqanKz2zfD4Bi62MS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2157,
      "cache_read_input_tokens": 79252,
      "output_tokens": 527,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 527,
          "cache_read_input_tokens": 79252,
          "cache_creation_input_tokens": 2157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2157
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

_source line 68 · 2026-05-24T12:17:46.807Z_

<details><summary>↩ Tool result · `toolu_017kDgTXLRkARtwp8GQdSugD`</summary>

```text
85:This is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c0a4c592-5d4d-46ad-8df9-e206b2dbe42e",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "ff14158d-fda9-4003-bc38-9e6247fe5ae3",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "85:This is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "c0a4c592-5d4d-46ad-8df9-e206b2dbe42e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 69 · 2026-05-24T12:17:43.030Z_

<details><summary>↩ Tool result · `toolu_01HEjqsHipGeseHPfdkScHyQ`</summary>

```text
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex:16:Our approach requires no access to model weights, logits, or training data---only binary response patterns and externally calibrated item parameters from PSN-IRT \citep{psnirt2026}.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex:4:For practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \emph{which} items drive aberrance rather than merely flagging contamination.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex:19:$\ell_z^*$ sits below MIA \citep[logits;][]{minkprob2024} and ConStat \citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot confirms this: Min-K\% AUC drops to chance ($0.493$) post-RL while $\ell_z^*$ signal persists (${\sim}3.3$; Figure~\ref{fig:grpo}), consistent with \citet{wang2025fragility}.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex:39:Qwen's contaminated $\ell_z^*$ at 15\% ($+3.84$) remains positive---absolute thresholding would miss it; \irtfit{} detects contamination through the within-family shift $\Delta\ell_z^*{=}{-}4.84$.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex:63:Guttman errors & Binary + $b$ & --- & --- \\
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex:64:QLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:109:The $|\Delta d| = 2.32$ gap at 50\% contamination reflects Qwen's non-monotonic dose-response (the $\theta$-shift boundary condition; \S\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:139:This stark asymmetry---95\% aberrance by $\ell_z^*$ versus 7\% by accuracy---motivates the $\Delta\ell_z^*$ matched-difference design (\S\ref{sec:did}), which sidesteps absolute thresholds by comparing each model against its own clean baseline.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:173:IRT person-fit statistics assume local independence---conditional on $\theta$, item responses are independent.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:226:The 50\% contamination condition under free-$\theta$ is fragile---consistent with its already-weak signal due to $\theta$-shift absorption (\S\ref{sec:inverted_u}).
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:228:Under $\theta$-fixed estimation (Table~\ref{tab:param_noise_fixed}), detection is highly robust: 10\% perturbation produces ${<}4\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\% contamination) and $12.20$ (50\%)---both far exceeding conventional thresholds.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:241:0\% & $-$6.575 & --- & $-$1.897 & --- \\
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:258:0\% & 4.77 & --- & 14.52 & --- \\
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:270:The single condition where BCa widens the zero-crossing set---Llama fixed-$\theta$ at 50\% contamination, BCa CI [$-$0.13, 2.21] vs.\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \S\ref{sec:theta_dynamics}.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:276:With 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:306:Min-K\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\ell_z^*$ detects persists.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex:13:No existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex:15:In this work, we focus on SFT-stage contamination---where benchmark answers are explicitly included in fine-tuning data---for three reasons.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:29:Llama$^{\dagger}$ & MMLU & --- & $-2.80$ ($\pm$0.60) & $-2.56$ ($\pm$0.52) & $-2.30$ ($\pm$0.30) \\
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:30:Mistral$^{\dagger}$ & MMLU & --- & $-3.37$ ($\pm$0.68) & --- & $-4.09$ ($\pm$0.53) \\
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:31:Qwen$^{\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:47:The cross-family variation in Table~\ref{tab:cohens_d}---Qwen's $|d|$ declining from 25\% to 50\% while Llama's remains flat---suggests detection sensitivity depends on more than contamination dose.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:50:The magnitude of $\theta$-shift is comparable across families---Qwen ($\Delta\theta{=}0.47$ at 50\%) and Llama ($\Delta\theta{=}0.52$)---yet their fixed-$\theta$ amplification diverges markedly (Table~\ref{tab:theta_fixed}), indicating that $\theta$-shift magnitude alone does not predict fixed-$\theta$ benefit.
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:127:(c) \emph{structural sensitivity}: on real leaderboard data, $\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\Delta\ell_z^*$ matched-difference design (\S\ref{sec:did}; Appendix~\ref{app:leaderboard_aberrance}).
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:169:  \caption{Dose-response trajectories for Cohen's $|d|$ on MMLU. Qwen free-$\theta$ (circles) exhibits non-monotonic behavior---signal peaks at 25\% then declines as $\theta$-shift absorbs the aberrance. Fixed-$\theta$ anchoring (squares, dashed) eliminates the artifact and reveals monotonic dose-response. Llama (triangles) shows a flat trajectory. Error bars: $\pm$1\,SD across $n{=}3$ training seeds; bands: $\pm$1\,SD envelope. Hollow markers at 5\%: single-seed.}
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:174:The mechanism is predictable from simulation (Appendix~\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\hat{\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5ce7d777-35bb-4877-88a3-c22a55040242",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "d9157f44-3465-4f04-8cc5-167b4e1f13be",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex:16:Our approach requires no access to model weights, logits, or training data---only binary response patterns and externally calibrated item parameters from PSN-IRT \\citep{psnirt2026}.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex:4:For practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \\emph{which} items drive aberrance rather than merely flagging contamination.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex:19:$\\ell_z^*$ sits below MIA \\citep[logits;][]{minkprob2024} and ConStat \\citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot confirms this: Min-K\\% AUC drops to chance ($0.493$) post-RL while $\\ell_z^*$ signal persists (${\\sim}3.3$; Figure~\\ref{fig:grpo}), consistent with \\citet{wang2025fragility}.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex:39:Qwen's contaminated $\\ell_z^*$ at 15\\% ($+3.84$) remains positive---absolute thresholding would miss it; \\irtfit{} detects contamination through the within-family shift $\\Delta\\ell_z^*{=}{-}4.84$.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex:63:Guttman errors & Binary + $b$ & --- & --- \\\\\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex:64:QLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:109:The $|\\Delta d| = 2.32$ gap at 50\\% contamination reflects Qwen's non-monotonic dose-response (the $\\theta$-shift boundary condition; \\S\\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:139:This stark asymmetry---95\\% aberrance by $\\ell_z^*$ versus 7\\% by accuracy---motivates the $\\Delta\\ell_z^*$ matched-difference design (\\S\\ref{sec:did}), which sidesteps absolute thresholds by comparing each model against its own clean baseline.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:173:IRT person-fit statistics assume local independence---conditional on $\\theta$, item responses are independent.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:226:The 50\\% contamination condition under free-$\\theta$ is fragile---consistent with its already-weak signal due to $\\theta$-shift absorption (\\S\\ref{sec:inverted_u}).\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:228:Under $\\theta$-fixed estimation (Table~\\ref{tab:param_noise_fixed}), detection is highly robust: 10\\% perturbation produces ${<}4\\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\\% contamination) and $12.20$ (50\\%)---both far exceeding conventional thresholds.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:241:0\\% & $-$6.575 & --- & $-$1.897 & --- \\\\\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:258:0\\% & 4.77 & --- & 14.52 & --- \\\\\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:270:The single condition where BCa widens the zero-crossing set---Llama fixed-$\\theta$ at 50\\% contamination, BCa CI [$-$0.13, 2.21] vs.\\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \\S\\ref{sec:theta_dynamics}.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:276:With 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex:306:Min-K\\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\\ell_z^*$ detects persists.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex:13:No existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex:15:In this work, we focus on SFT-stage contamination---where benchmark answers are explicitly included in fine-tuning data---for three reasons.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:29:Llama$^{\\dagger}$ & MMLU & --- & $-2.80$ ($\\pm$0.60) & $-2.56$ ($\\pm$0.52) & $-2.30$ ($\\pm$0.30) \\\\\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:30:Mistral$^{\\dagger}$ & MMLU & --- & $-3.37$ ($\\pm$0.68) & --- & $-4.09$ ($\\pm$0.53) \\\\\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:31:Qwen$^{\\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\\\\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:47:The cross-family variation in Table~\\ref{tab:cohens_d}---Qwen's $|d|$ declining from 25\\% to 50\\% while Llama's remains flat---suggests detection sensitivity depends on more than contamination dose.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:50:The magnitude of $\\theta$-shift is comparable across families---Qwen ($\\Delta\\theta{=}0.47$ at 50\\%) and Llama ($\\Delta\\theta{=}0.52$)---yet their fixed-$\\theta$ amplification diverges markedly (Table~\\ref{tab:theta_fixed}), indicating that $\\theta$-shift magnitude alone does not predict fixed-$\\theta$ benefit.\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:127:(c) \\emph{structural sensitivity}: on real leaderboard data, $\\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\\Delta\\ell_z^*$ matched-difference design (\\S\\ref{sec:did}; Appendix~\\ref{app:leaderboard_aberrance}).\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:169:  \\caption{Dose-response trajectories for Cohen's $|d|$ on MMLU. Qwen free-$\\theta$ (circles) exhibits non-monotonic behavior---signal peaks at 25\\% then declines as $\\theta$-shift absorbs the aberrance. Fixed-$\\theta$ anchoring (squares, dashed) eliminates the artifact and reveals monotonic dose-response. Llama (triangles) shows a flat trajectory. Error bars: $\\pm$1\\,SD across $n{=}3$ training seeds; bands: $\\pm$1\\,SD envelope. Hollow markers at 5\\%: single-seed.}\n/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex:174:The mechanism is predictable from simulation (Appendix~\\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\\hat{\\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.",
    "numLines": 26
  },
  "sourceToolAssistantUUID": "5ce7d777-35bb-4877-88a3-c22a55040242",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 70 · 2026-05-24T12:17:44.106Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01B6WKRwg66XYhxNjqB2XxJB`</summary>

```json
{
  "pattern": "(?i)(significantly|state.of.the.art|consistently|remarkably|groundbreaking|revolutionary)",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d9157f44-3465-4f04-8cc5-167b4e1f13be",
  "isSidechain": false,
  "requestId": "req_011CbMNyaookeASdNvteWMiv",
  "type": "assistant",
  "uuid": "febf3370-66e6-414b-b2a0-c02355297fd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C1jUMHqanKz2zfD4Bi62MS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2157,
      "cache_read_input_tokens": 79252,
      "output_tokens": 527,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 527,
          "cache_read_input_tokens": 79252,
          "cache_creation_input_tokens": 2157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2157
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

_source line 71 · 2026-05-24T12:17:44.140Z_

<details><summary>↩ Tool result · `toolu_01B6WKRwg66XYhxNjqB2XxJB`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "febf3370-66e6-414b-b2a0-c02355297fd5",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "66a10da8-4c2c-4d65-ab3b-319a8ee1b8c0",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "febf3370-66e6-414b-b2a0-c02355297fd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 72 · 2026-05-24T12:17:45.655Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Cf2icGQp7owxRyHV2feUhx`</summary>

```json
{
  "pattern": "\\\\section",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "66a10da8-4c2c-4d65-ab3b-319a8ee1b8c0",
  "isSidechain": false,
  "requestId": "req_011CbMNyaookeASdNvteWMiv",
  "type": "assistant",
  "uuid": "fefff950-b64e-41f1-b071-e0521ec8cb8c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C1jUMHqanKz2zfD4Bi62MS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2157,
      "cache_read_input_tokens": 79252,
      "output_tokens": 527,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 527,
          "cache_read_input_tokens": 79252,
          "cache_creation_input_tokens": 2157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2157
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

_source line 73 · 2026-05-24T12:17:45.670Z_

<details><summary>↩ Tool result · `toolu_01Cf2icGQp7owxRyHV2feUhx`</summary>

```text
1:\section{Simulation Validation}
12:\section{4PL vs.\ 3PL Ablation Details}
52:\section{Seed Sensitivity Analysis}
126:\section{Baseline $\ell_z^*$ Interpretation}
133:\section{Leaderboard Aberrance Analysis}
141:\section{Item-Level Detection Results}
167:\section{Robustness Analysis}
265:\section{BCa Bootstrap Sensitivity Check}
272:\section{Classical IRT Refit from Leaderboard Data}
300:\section{Post-RL Preliminary Observation}
344:\section{QLoRA Training Hyperparameters}
377:\section{Contamination Run Reproducibility}\label{app:reproducibility}
473:\section{Use of AI Assistants}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fefff950-b64e-41f1-b071-e0521ec8cb8c",
  "isSidechain": false,
  "promptId": "ffab3485-6b13-4495-803c-b41c3f2ea9ad",
  "type": "user",
  "uuid": "ccb342fc-a172-4008-b8f3-3f7865ab9490",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "1:\\section{Simulation Validation}\n12:\\section{4PL vs.\\ 3PL Ablation Details}\n52:\\section{Seed Sensitivity Analysis}\n126:\\section{Baseline $\\ell_z^*$ Interpretation}\n133:\\section{Leaderboard Aberrance Analysis}\n141:\\section{Item-Level Detection Results}\n167:\\section{Robustness Analysis}\n265:\\section{BCa Bootstrap Sensitivity Check}\n272:\\section{Classical IRT Refit from Leaderboard Data}\n300:\\section{Post-RL Preliminary Observation}\n344:\\section{QLoRA Training Hyperparameters}\n377:\\section{Contamination Run Reproducibility}\\label{app:reproducibility}\n473:\\section{Use of AI Assistants}",
    "numLines": 13
  },
  "sourceToolAssistantUUID": "fefff950-b64e-41f1-b071-e0521ec8cb8c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 74 · 2026-05-24T12:17:46.798Z_

<details open><summary>🔧 Tool call — Grep · `toolu_017kDgTXLRkARtwp8GQdSugD`</summary>

```json
{
  "pattern": "(?i)limitation",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ccb342fc-a172-4008-b8f3-3f7865ab9490",
  "isSidechain": false,
  "requestId": "req_011CbMNyaookeASdNvteWMiv",
  "type": "assistant",
  "uuid": "c0a4c592-5d4d-46ad-8df9-e206b2dbe42e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C1jUMHqanKz2zfD4Bi62MS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2157,
      "cache_read_input_tokens": 79252,
      "output_tokens": 527,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 527,
          "cache_read_input_tokens": 79252,
          "cache_creation_input_tokens": 2157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2157
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

_source line 75 · 2026-05-24T12:17:46.890Z_

```json
{
  "parentUuid": "ff14158d-fda9-4003-bc38-9e6247fe5ae3",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "fd388ee0-6b92-411f-88f2-1901e31a5c83",
  "timestamp": "2026-05-24T12:17:46.890Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 76_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper  Phase 1 确定性检查结果： 源码检查: passed=False, 1 critical, 1 warning 一致性检查:…",
  "leafUuid": "fd388ee0-6b92-411f-88f2-1901e31a5c83",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 77_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Assistant

_source line 78 · 2026-05-24T12:22:18.503Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the data I need to perform the content audit. Let me go through each dimension systematically.

## 1. Narrative Consistency (CRITICAL)

Let me cross-reference the core story across chapters:

**Abstract's "problem"**: Benchmark contamination undermines evaluation validity; most detection methods require privileged access.
**Intro's "problem"**: Same - benchmark contamination, existing methods require privileged access. ✓ Consistent.

**Intro's "contribution list"**:
1. First empirical characterization of IRT person-fit behavior for LLM contamination (θ-shift absorption, detection-diagnosis tradeoff)


2. Δℓz* reliably detects SFT-stage contamination across three model families
3. Detection-diagnosis tradeoff documentation

**Method actually does**: IRT person-fit framework with 4PL, Δℓz* matched-difference design, experimental setup with 3 model families, MMLU and ARC-C.
✓ Matches contributions.

**Method's "why this design"**: LLMs violate IRT assumptions (57/60 cells aberrant), so matched-difference design needed. Intro's "gap": no method operates on binary response patterns alone.
✓ Consistent.

**Experiments**: Now checking whether the experimental results actually validate each claimed contribution and whether the narrative flows logically from problem through method to findings. The Discussion covers the broader implications across different tools, practical applications, calibration considerations, and what information is needed. The Conclusion ties together all three main findings and recommends a two-stage workflow approach. The structure holds together well—there's no significant narrative drift between sections, though the Abstract's phrasing of "three behavior boundaries" is slightly more specific than how the Conclusion frames them, which is acceptable.

I'm noticing a subtle distinction in how the contributions map to the findings. The Introduction lists three contributions that reorganize the findings slightly: the first characterization of θ-shift absorption, the reliability of Δℓz* for detection, and the detection-diagnosis tradeoff. These overlap with but aren't identical to the three core findings about θ-shift dynamics, the detection-diagnosis tradeoff, and non-monotonic dose-response patterns.

There's also an important detail about clean baselines that I want to verify is consistent throughout. The Abstract states that diagnostic θ-anchoring requires a clean baseline, and the Methods section distinguishes between controlled experiments with clean baselines—where Δℓz* is computed directly—and deployment scenarios without them, where cross-benchmark comparison serves as the reference. This isn't framed as a hard constraint on the entire framework, but rather as a requirement specific to the θ-anchoring step. Basic detection operates at a different level and doesn't depend on this. The framing is consistent: clean baselines are preferred for θ-anchoring but not mandatory for the detection component itself.

Now I'm checking the Abstract against the four standard components. It covers the problem (benchmark contamination and the access limitation of existing methods), the method (IRT person-fit statistics and the Δℓz* matched-difference design), the results (three behavior boundaries with specific numbers), and the significance statement about when binary response patterns carry contamination information). The word count is 198, which stays under the 200-word limit.

For the Introduction structure, I'm seeing roughly five paragraphs: background on contamination as a growing threat, the problem that existing methods require privileged access, the rationale for focusing on SFT, motivation from RL failures of current approaches, and our key observation about the IRT person-fit analogy.

The Related Work section uses thematic grouping rather than listing individual contributions—organizing around benchmark contamination detection, IRT applications to LLM evaluation, and person-fit statistics in psychometrics.

Checking the contributions against what the results actually deliver: the first contribution about empirically characterizing IRT person-fit behavior is well-supported throughout the results sections, the second about Δℓz* reliably detecting SFT-stage contamination across model families is covered in Table 1 and section 5.1, and the detection-diagnosis tradeoff appears in section 5.3.

Now I'm verifying that the non-monotonic dose-response finding in section 5.4 isn't orphaned—it's marked as exploratory but still falls under the empirical characterization contribution from the intro, so it fits the scope. The title directly answers what IRT person-fit statistics reveal about contamination, and the experiments match the stated scope of three 7-8B model families. The claims avoid overclaiming like "state-of-the-art" and stick to what's actually demonstrated, like "reliably detects."

The "first controlled characterization" claim in the abstract checks out given the literature review confirms no prior work has applied person-fit statistics to this problem. For experimental rigor, multi-seed results report standard deviation across n=3 runs, while single-seed conditions use bootstrap 95% confidence intervals.

The baselines are current, pulling from 2024-2026 publications. The ablations are comprehensive—comparing 4PL versus 3PL models, free versus fixed parameters, multiple statistics, varying contamination levels, and testing robustness to local dependence and parameter perturbations. Reproducibility is well-documented with full hyperparameters in the appendix and specific software versions (PyTorch 2.8.0, Transformers 5.8.1, PEFT 0.19.1, BitsAndBytes 0.49.2) listed in the reproducibility statement.

Random seeds are specified (42, 123, 456), and data preprocessing details including item selection and nesting are clear, though GPU requirements and training time aren't mentioned. For terminology, the symbols are consistently used throughout—θ for ability, ℓz* for person-fit statistics, Δℓz* for matched differences—though there's a potential ambiguity where d appears both as the 4PL upper asymptote parameter (subscripted as d_i) and as Cohen's d for effect sizes, though the subscripting helps distinguish them. The subscript distinction makes it clear enough, but both share the same letter.

Actually, let me check if the paper explicitly addresses this. In method.tex line 13: "where $a_i$ is discrimination, $b_i$ difficulty, $c_i$ the lower asymptote (guessing), and $d_i$ the upper asymptote (slip)." And then later "effect sizes as $d = ...$". There's no explicit note about the symbol overload. This could confuse readers.

Wait - actually, in the contributions, they write "$\ell_z^*$'s diagnostic capabilities" using possessive with a math symbol. That's stylistically awkward but not really a symbol consistency issue.

The chapter transitions flow reasonably well overall. Introduction moves into Related Work naturally, though there's no explicit bridge sentence connecting them. Related Work transitions into Method with a decent connection between the contamination detection discussion and the 4PL IRT model adoption. Results and Discussion follow logically from there, and the Conclusion wraps things up appropriately.

The Limitations section is quite brief at around 95 words. Looking at what's actually covered, I can identify a few distinct limitations mentioned, including the scope of model families tested with QLoRA, though the list seems to cut off mid-point. I'm checking the AI style guidelines now, specifically looking at em-dash usage across the document files. I'm finding quite a few instances of the LaTeX em-dash (---) scattered throughout the main text sections—about 11 total across introduction, related work, method, results, discussion, and conclusion. That's a significant number to consider for consistency. I'm seeing the rest of the em-dash issues throughout the document—there are about seven more instances in the main text where em-dashes are being used for explanatory purposes instead of proper punctuation. The pattern is consistent: these dashes appear between clauses that should use commas, parentheses, or other standard punctuation. This is a significant style violation that needs to be corrected across all instances.

Looking at the other checks, the filler words and AI blacklist terms are clean, and the "additionally" usage is fine since it's functioning as a regular adverb rather than a problematic discourse connector. The main remaining issue is that participial clause ending in the conclusion that needs fixing, along with the broader em-dash problem throughout.

Now I'm doing a more careful count of em-dashes across the document sections. I can see several instances scattered through the introduction, related work, methods, and results—they're appearing in contexts like "training data---though" and "contamination---where" where they're being used to separate clauses. The results section appears to have one that's cut off mid-line, so I need to see the full context there.

Looking at the discussion and conclusion, there are a few more instances. Altogether this adds up to around a dozen em-dashes in the main text, which is starting to feel like overuse and worth flagging as a warning-level concern.

The appendix structure looks good—there's only one limitations section in the main text as required, not duplicated in the appendix. The abstract is sitting at 198 words, which keeps it under the 200-word limit, though I should verify the exact word count methodology being used.

Now I need to cross-check the specific values mentioned in the introduction against what's actually shown in Table 2 to make sure the claims about Qwen's performance improvements and the inter-seed coefficient of variation are accurate.

Looking at the section structure, the document follows a standard academic paper format with introduction through conclusion, and I'm checking that the numbering and organization in main.tex aligns properly with the content flow.

I notice there are several orphaned files in the sections directory—background.tex, experiments.tex, and a few others—that aren't actually included in main.tex, so they're likely leftovers from an earlier draft.

Now I'm verifying that the three contributions listed in the introduction are properly supported throughout the paper.  The first contribution about empirical characterization is backed by results in sections 5.1, 5.2, and 5.4 plus appendix analyses; the second about Δℓz* detection is supported by Table 1 where all confidence intervals exclude zero; and the third about the detection-diagnosis tradeoff is covered in Table 3 and section 5.3.

The scope claims in the abstract match what's actually tested—three model families of 7-8B parameters, evaluated on MMLU and ARC-Challenge—and the title frames this appropriately as a research question rather than a broad claim.

For positioning against related work, the paper makes a clear distinction that no existing method relies solely on binary response patterns for this kind of analysis, and none have applied person-fit statistics specifically to contamination detection.

Now I'm spot-checking the numeric claims throughout the paper: the 2.4× amplification mentioned in the abstract matches Table 2, the inter-seed coefficient of variation dropping from about 60% to 19% aligns with the appendix data, the flagged cell counts of 57/60 versus 4/60 are confirmed in section 5.3, and the Qwen effect size of -4.15 appears in Table 1.

I notice the letter $d$ does double duty here—it's both the upper asymptote parameter in the 4PL model and Cohen's $d$ effect size throughout the results, though the subscripting helps distinguish them in context.

The Discussion section goes beyond just restating numbers; it actually interprets the findings by positioning the characterization relative to existing tools, drawing out practical implications for practitioners, and honestly discussing the scope and calibration limitations.

Looking at the overall assessment, there aren't any critical issues with the narrative consistency. The main concerns are the frequent em-dashes in the text (which read as a stylistic marker), the potential confusion from reusing $d$ for different purposes, and a few reproducibility gaps like missing GPU specifications and training time. The Limitations section is brief but aligns with the stated requirement for a short paragraph, though one conclusion about response-pattern anomalies rests on just a single observation.

Checking the hedging language more carefully—the conclusion presents "persist" as definitive when the underlying GRPO finding is explicitly N=1 and acknowledged in the Appendix as needing broader validation. The phrasing should better reflect that limitation rather than stating it as an established fact. There are also some orphaned LaTeX files not connected to the main document, and a few stylistic quirks like the em-dash combined with an "-ing" phrase that reinforce the AI-written feel. The conclusion frames person-fit statistics as a general capability without acknowledging that the method still depends on externally calibrated item parameters—a dependency that's properly qualified elsewhere in the paper but gets lost in the final summary.

Looking at the three behavioral boundaries from the abstract, they map cleanly to the results sections: the model-specific θ-shift dynamics, the detection-diagnosis tradeoff, and the ability-dependent dose-response patterns all have corresponding evidence. Now I'm checking whether the abstract's specific claims about performance metrics like the 57/60 figure actually appear in the results.

The introduction's claim that simpler statistics yield stronger detection but lack diagnostic power checks out against Table 3, which shows much larger effect sizes for accuracy z-scores. One thing I'm noticing though is that Table 1 mixes single-seed and multi-seed conditions, and while the footnote explains this, the main text sometimes cites these numbers without clarifying which type is being referenced. I see the table is using a dagger symbol to mark all rows, but the footnote clarifies that only certain conditions within those rows are multi-seed with standard deviations—the rest use single-seed bootstrap confidence intervals. Looking at the actual formatting, Qwen's 5% column shows a bootstrap CI in brackets, while the 15%, 25%, and 50% columns show ±SD notation indicating multiple runs, and the same pattern applies across the other models. Looking at the appendix reproducibility tables, I can see that all three model families actually have multi-seed contamination runs—Qwen, Llama, and Mistral each show n=3 seeds for their contamination levels. So the $\dagger$ marking is correct across the board. But the Method section's wording about "for Qwen, each contamination level... was additionally replicated" is misleading since the same multi-seed approach was applied to all three models, not just Qwen. Looking at the table footnotes more carefully, I see that both Table 1 and Table 2 explicitly mark which conditions used multi-seed runs (n=3) versus single-seed with bootstrap CIs. So the data presentation is actually consistent—the issue is that the Method section only explicitly mentions Qwen's multi-seed replication when the tables show this was done across all three models for certain conditions. This is a narrative gap where the experimental design description doesn't fully match what the data reveals. Looking at the Method section again, it explicitly states the n=3 contamination seed replication was done "for Qwen," but the appendix tables show Llama and Mistral also have 3 seeds per contamination level, which creates a genuine discrepancy between what the text claims and what the data actually shows. The Introduction actually does cite multi-seed means for Llama, which suggests the multi-seed replication happened across all three models, but the Method section only explicitly describes it for Qwen. This is a narrative inconsistency—either the Method wasn't updated after expanding the replication, or the Introduction is overstating what was pre-planned. Let me compile my final audit findings now, starting with the critical issues and then moving through the warnings I've identified. I'm noticing some notation conflicts—$d_i$ and $d$ both use the same letter which could trip up readers unfamiliar with psychometrics or statistics. The reproducibility section is also missing key details like GPU specifications and total compute hours, even though software versions are documented. There's a stylistic quirk in the conclusion with an em-dash followed by a participial phrase that reads a bit awkwardly. The limitations section hits the expected scope at around 95 words covering three main points, though I'm seeing several orphaned .tex files scattered in the sections directory that might need consolidation.

The abstract is running close to the 200-word EMNLP limit at 198 words, so I should double-check the actual rendered count from the PDF since LaTeX commands can affect the final tally. One more thing I'm catching—the methods section mentions extending the 25% condition to Llama to test generalization, but the multi-seed aspect with n=3 contamination seeds is only explicitly described for Qwen, which creates an inconsistency when looking at how the standard deviations are presented for Llama and Mistral in the tables.

Actually, looking more carefully at Table 1, both Llama and Mistral clearly show standard deviations across multiple contamination levels, which means they must have had n=3 runs as well. So the experimental design was applied more broadly than the Method section describes—this is a genuine gap between what the text claims and what the data shows. The Related Work does position the contribution well though, clearly distinguishing this work from prior IRT applications and contamination detection approaches. The Abstract findings match up with what I'm laying out in the Introduction—the θ-shift dynamics with the specific amplification metrics, the detection-diagnosis tradeoff, and the non-monotonic dose-response pattern all align. Everything checks out consistently. Now I'm verifying the numerical consistency in Table 2 across the different conditions—checking that the ratios between free and fixed effect sizes match what's reported, and so far the calculations are checking out. I see the footnote clarifies that Table 2 uses single-seed results from seed 42, while Table 1 reports multi-seed means—so they're intentionally different. The ratios in Table 2 should be comparing values from the same seed, making the comparison internally consistent.

Looking more closely at Mistral though, there's a wrinkle: the footnote indicates Mistral's free-θ uses all 10 clean seeds while fixed-θ only uses 6, so the ratio isn't actually comparing apples to apples for that model. Ah, so Table 1's Mistral 15% value of 3.37 (±0.68) is the average across three contamination runs, while Table 2's 2.64 is specifically seed 42's result—that's why they differ. Looking at the appendix, I can see seed 42 gives -2.64, seed 2 gives -3.98, and seed 3 gives -3.49, which average to -3.37, so everything checks out. Now let me verify whether the abstract and introduction mention "first" to complete my audit.

The abstract claims this is "the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination," and the introduction says "the first empirical characterization of IRT person-fit behavior for LLM contamination." The related work section confirms no prior work has applied person-fit statistics to LLM contamination, so this claim appears well-supported by the literature review. I should also confirm the paper distinguishes between the pre-planned findings and the exploratory post-hoc analysis.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fd388ee0-6b92-411f-88f2-1901e31a5c83",
  "isSidechain": false,
  "requestId": "req_011CbMNzCSvkwNSjNtMixc7s",
  "type": "assistant",
  "uuid": "78861a0d-9da1-41ef-b0fb-25eed3cfed53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0173zqaFz8hWKFNN3wQzVWae",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3873,
      "cache_read_input_tokens": 81409,
      "output_tokens": 14425,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3873,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 14425,
          "cache_read_input_tokens": 81409,
          "cache_creation_input_tokens": 3873,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3873
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

_source line 79 · 2026-05-24T12:23:17.357Z_

审计完成。以下是完整的结构化 findings。

```
[CONTENT_AUDIT_START]

=== 叙事一致性 (CRITICAL 维度) ===

- [warning] [叙事一致性] Method (method.tex:52) 仅描述 Qwen 做了 n=3 contamination seed 复制 ("for Qwen, each contamination level... was additionally replicated with n=3 independent QLoRA seeds")，但 Table 1 (results.tex:29-30) 展示 Llama 和 Mistral 同样以 ±SD 格式报告多种子均值，Appendix 中也有 llama_multiseed 和 mistral_multiseed 表。Introduction 引用了 Llama 的多种子均值 (|d|=2.80/2.56/2.30)。Method 的实验设计描述与实际呈现的数据不匹配——Method 需补充说明 Llama 和 Mistral 的多种子复制实验。

- [warning] [Claim强度] conclusion.tex:5 声称 "person-fit statistics capture response-pattern anomalies that persist after RL post-training erases memorization-based signals" 未加限定词，但 method.tex:61 明确标注 "This extension is N=1 (single model family, single contamination level)"，appendix.tex:307 更直接说 "This N=1 observation requires validation across model families, RL methods, and contamination levels before any conclusions can be drawn." Conclusion 需将此降级为 preliminary/pilot-level evidence。

- [info] [叙事一致性] Abstract/Intro/Method/Results/Discussion/Conclusion 的核心 story（问题-方法-发现）高度一致。三个 findings、三个 contributions 在各章节间无漂移。"exploratory" 标签在 Abstract (行7)、Intro (行53)、Results (行163) 一致标注。

=== 去 AI 风格 ===

- [warning] [去AI] 主文 em-dash (---) 共约 12 处，覆盖 6 个 section 文件。这是最显著的 AI 写作标志。具体位置：
  introduction.tex:13 "training data---though"
  introduction.tex:15 "contamination---where"
  related_work.tex:16 "training data---only"
  method.tex:64 "mixtures---analogous"
  results.tex:47 "flat---suggests"
  results.tex:50 "families---Qwen" 和 "---yet"
  results.tex:127 "aberrant---evidence"
  results.tex:169 "behavior---signal" (caption)
  results.tex:174 "anomaly---but"
  discussion.tex:19 "bank---suited"
  conclusion.tex:4 "needed---distinguishing"
  每处应改为逗号、括号或拆分为两句。Appendix 中另有约 7 处文本 em-dash，但优先修正主文。

- [info] [去AI] conclusion.tex:4 "needed---distinguishing \emph{which} items drive aberrance rather than merely flagging contamination" 同时触发 em-dash + -ing 分词短语模式。建议重写为两个独立句子。

- [info] [去AI] 无 Unicode em-dash (—)、无 filler words (notably/importantly/it is worth noting)、无黑名单用词 (delve/leverage/utilize)、无连续过渡词 (furthermore/moreover/additionally)。整体去 AI 风格做得较好，em-dash 是唯一系统性残留。

=== 符号/术语一致性 ===

- [info] [符号] $d_i$ (4PL 上渐近线参数, method.tex:13) 与 $d$ (Cohen's d 效应量, results.tex 全篇) 共用同一字母。虽有下标区分，但跨领域读者可能混淆。考虑将 4PL 上渐近线改用 $u_i$ 以消除歧义（psychometrics 文献中 $u$ 是常见替代符号）。

=== 章节结构 ===

- [info] [章节结构] Abstract 完整回答四个问题（问题/方法/结果/意义），Introduction 遵循 5+ 段结构（背景→问题→为什么SFT→RL动机→IRT类比→findings→contributions），Related Work 按三个主题归纳（contamination detection / IRT for LLMs / person-fit psychometrics）。结构符合规范。

=== 贡献-范围对齐 ===

- [info] [贡献-范围] Introduction 三条 contribution 均有对应：(1)→Results全篇+Appendix, (2)→Table 1 + §5.1, (3)→Table 3 + §5.3。无孤儿章节。Title/Abstract 范围词 "three 7--8B model families" 与实验实际覆盖一致。

=== 实验严谨性 ===

- [info] [实验严谨性] 主结果 (Table 1) 对多种子条件报告 ±SD，对单种子条件报告 bootstrap 95% CI (10,000 resamples)。Baseline 引用覆盖 2024-2026 近期工作。Ablation 覆盖 4PL vs 3PL (Appendix)、free-θ vs fixed-θ (Table 2)、三种统计量对比 (Table 3)、local dependence robustness、parameter perturbation。

=== 可复现性 ===

- [warning] [可复现性] Reproducibility Statement (main.tex:42-47) 列出了软件版本 (PyTorch 2.8.0 等) 和 bootstrap 参数，但缺少 GPU 型号、单实验训练时间、总 GPU-hours。EMNLP checklist 通常要求这些信息。建议在 Appendix 的 hyperparameters 表中补充。

=== Limitations 诚实度 ===

- [info] [Limitations] 约 95 words，覆盖 3 个 distinct limitations（模型规模/架构泛化、单种子/N=1限制、PSN-IRT依赖/无head-to-head对比）。按用户自定义 EMNLP 规则 "只需要写一小段，覆盖 3 个点左右" 合规。内容实质性，无回避式表述。

=== 章节过渡与逻辑流 ===

- [info] [章节过渡] Discussion 不重复 Results 数字，而是做更高层解读（characterization over tool / practical implications / scope and calibration / information requirements positioning）。各章节间过渡自然。

=== 内部信息残留 ===

- [info] [内部信息] 未发现实验编号 (exp_xxx)、服务器名、内部 IP、框架内部术语、不当隐含流程引用。AI 使用声明 (Appendix §Use of AI Assistants) 正确披露。

=== 用户自定义规则检查 ===

- [info] [写作规则] Abstract 约 198 words (wc 原始计数含 LaTeX 命令)，应在 200 word 限制内但接近边界。建议用编译后 PDF 的渲染文本再次确认精确字数。

- [info] [写作规则] Limitations section 仅一个，位于正文 (main.tex:39 \input{sections/limitations})，Appendix 中无额外 limitations section。合规。

- [info] [写作规则] 论文 PDF 中未包含 ARR Responsible NLP Checklist（应在 OpenReview submission form 中手动填写）。合规。

- [info] [审稿规则] 总页数 16 页（编译结果），主文约 8 页 + references + appendix。需确认主文（不含 limitations 和 references）≤ 8 页。

[CONTENT_AUDIT_END]
```

**审计总结**：

- **Critical: 0** — 叙事一致性高度完整，无重大结构性问题
- **Warning: 4** — (1) Method 未描述 Llama/Mistral 多种子复制; (2) Conclusion 对 N=1 GRPO 结果过度声称; (3) 主文 12 处 em-dash; (4) 缺少 GPU/训练时间信息
- **Info: 12** — 符号歧义、Abstract 字数边界、结构合规确认等

[AUDIT_DONE]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "78861a0d-9da1-41ef-b0fb-25eed3cfed53",
  "isSidechain": false,
  "requestId": "req_011CbMNzCSvkwNSjNtMixc7s",
  "type": "assistant",
  "uuid": "73505218-ac12-42f6-95e7-e8eabbec0be8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/.claude/sessions/paper_audit_content_a705c4ee",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0173zqaFz8hWKFNN3wQzVWae",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3873,
      "cache_read_input_tokens": 81409,
      "output_tokens": 14425,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3873,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 14425,
          "cache_read_input_tokens": 81409,
          "cache_creation_input_tokens": 3873,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3873
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
  "lastPrompt": "项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper  Phase 1 确定性检查结果： 源码检查: passed=False, 1 critical, 1 warning 一致性检查:…",
  "leafUuid": "73505218-ac12-42f6-95e7-e8eabbec0be8",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 81_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 82_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：irt_personfit_contam Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper  Phase 1 确定性检查结果： 源码检查: passed=False, 1 critical, 1 warning 一致性检查:…",
  "leafUuid": "73505218-ac12-42f6-95e7-e8eabbec0be8",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

### Runtime record

_source line 83_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 paper compliance audit",
  "sessionId": "e9a6f4dc-28b0-4890-b409-6b9949e65d46"
}
```

---

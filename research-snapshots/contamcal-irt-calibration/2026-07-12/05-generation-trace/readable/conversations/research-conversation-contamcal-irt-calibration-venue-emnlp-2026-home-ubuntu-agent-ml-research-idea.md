# Research conversation: 项目：contamcal-irt-calibration Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-i

**Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 79
- **Recorded user turns:** 1
- **Tool calls:** 25
- **Original source:** `logs/chats/exported-trajectories/account-2/1e2075ff-846f-45a6-9f90-c21d252fe0bd.jsonl`
- **Structured JSON:** [`301bfaa6acbb540679b3.json`](../../sessions/30/301bfaa6acbb540679b3.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-25T09:53:31.508Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-25T09:53:31.508Z",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "content": "项目：contamcal-irt-calibration\nVenue：emnlp-2026\n论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper\n\nPhase 1 确定性检查结果：\n源码检查: passed=True, 0 critical, 39 warning\n一致性检查: 0 critical, 4 warning\n编译: ✅, 页数: 21\n内部信息: 0 critical, 0 warning\n\n━━━ 用户自定义规则（作为额外检查项）━━━\n## 用户自定义规则（必须遵守）\n### 写作规则\n\n- **[EMNLP 2026]** Limitations 章节只需要写一小段，覆盖 3 个点左右就可以了，不需要写得很长\n- **[EMNLP 2026]** ARR Responsible NLP Checklist在OpenReview的submission form里面（由用户手动填写），而不是在论文pdf里面\n- **[EMNLP 2026]** 一篇文章只能有一个limitations section，放在正文里面，appendix不能有 limitations section\n- **[EMNLP 2026]** abstract 不要超过 200 words\n\n### 审稿规则\n\n- **[EMNLP 2026]** “EMNLP 2026 通过 ARR 统一审稿，Main/Findings 不分开投稿（不是两个Track），Long/Short 也走同一审稿系统，Overall Assessment的评分标准如下：5 = Consider for Award（约前2.5%），4.5 = Borderline Award，4 = Conference（可被主会议接收），3.5 = Borderline Conference，3 = Findings（可被Findings接收），2.5 = Borderline Findings，2 = Resubmit next cycle（需大幅修改，可在下一周期完成），1.5 = Resubmit after next cycle（需大幅修改，无法在下一周期完成），1 = Do not resubmit（需完全重做或与*ACL无关）”\n- **[EMNLP 2026]** EMNLP 2026 restricts long paper submissions to a strict 8-page limit for main text, with unlimited space for references. Mandatory limitations and optional ethical considerations do not count towards this page limit, provided they do not contain excessive additional content.\n\n> 以上规则由用户配置，优先级等同于硬约束。违反会被 Reviewer 标记。\n请将以上规则逐条作为额外审计维度检查。违反的规则用 dimension `[写作规则]` 或 `[审稿规则]` 标记，severity 按实际影响判定。\n\n请按照你的角色指令执行内容结构审计。"
}
```

---

### Runtime record

_source line 2 · 2026-05-25T09:53:31.513Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-25T09:53:31.513Z",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

## Round 1

77 recorded events

### User

_source line 3 · 2026-05-25T09:53:31.559Z_

项目：contamcal-irt-calibration
Venue：emnlp-2026
论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper

Phase 1 确定性检查结果：
源码检查: passed=True, 0 critical, 39 warning
一致性检查: 0 critical, 4 warning
编译: ✅, 页数: 21
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
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "af595db3-e4fe-42e3-b0c4-52f57caa59fa",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-25T09:53:31.558Z_

```json
{
  "parentUuid": "af595db3-e4fe-42e3-b0c4-52f57caa59fa",
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
  "uuid": "47f32caa-f4ae-4885-b805-ed30c8711d11",
  "timestamp": "2026-05-25T09:53:31.558Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-25T09:53:31.559Z_

```json
{
  "parentUuid": "47f32caa-f4ae-4885-b805-ed30c8711d11",
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
  "uuid": "c0109294-a39b-49fc-8ce0-663f78cdd74c",
  "timestamp": "2026-05-25T09:53:31.559Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-25T09:53:31.559Z_

```json
{
  "parentUuid": "c0109294-a39b-49fc-8ce0-663f78cdd74c",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "0f330285-319f-4659-8de8-722786f97abc",
  "timestamp": "2026-05-25T09:53:31.559Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
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
  "aiTitle": "EMNLP 2026 contamcal-irt-calibration paper audit",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Assistant

_source line 8 · 2026-05-25T09:53:34.551Z_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the required skill files and then all the .tex files in the paper directory.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0f330285-319f-4659-8de8-722786f97abc",
  "isSidechain": false,
  "requestId": "req_011CbP5o6MHVH7V51dnWgE7v",
  "type": "assistant",
  "uuid": "5d87f65b-7b12-4f50-8926-a4618ce920a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KCARFsGsQzs2ekeuyj6ZBo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26930,
      "cache_read_input_tokens": 11846,
      "output_tokens": 286,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26930,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 286,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26930,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26930
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

_source line 9 · 2026-05-25T09:53:35.132Z_

开始执行内容结构审计。先加载审计标准和论文源码。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5d87f65b-7b12-4f50-8926-a4618ce920a9",
  "isSidechain": false,
  "requestId": "req_011CbP5o6MHVH7V51dnWgE7v",
  "type": "assistant",
  "uuid": "19ce796e-f3c3-4602-abc6-12de11797f66",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KCARFsGsQzs2ekeuyj6ZBo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26930,
      "cache_read_input_tokens": 11846,
      "output_tokens": 286,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26930,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 286,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26930,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26930
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

_source line 10 · 2026-05-25T09:53:35.666Z_

<details open><summary>🔧 Tool call — Read · `toolu_015kg5fe92NzMjTmgxeBGocD`</summary>

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
  "parentUuid": "19ce796e-f3c3-4602-abc6-12de11797f66",
  "isSidechain": false,
  "requestId": "req_011CbP5o6MHVH7V51dnWgE7v",
  "type": "assistant",
  "uuid": "24e09f36-811f-4b02-abae-b000bbb1aa6b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KCARFsGsQzs2ekeuyj6ZBo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26930,
      "cache_read_input_tokens": 11846,
      "output_tokens": 286,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26930,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 286,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26930,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26930
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

_source line 11 · 2026-05-25T09:53:36.878Z_

<details><summary>↩ Tool result · `toolu_01VA3tVfoUjQ6cmVFqQQuWSt`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/ethics.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/experimental_setup.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2a6af845-e769-41d0-8ea6-618d5117712a",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "78d2a0f1-0ae0-49b1-a463-d6ff20c8f694",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/ethics.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/related_work.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/abstract.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/method.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/experimental_setup.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/introduction.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex"
    ],
    "durationMs": 12,
    "numFiles": 11,
    "truncated": false
  },
  "sourceToolAssistantUUID": "2a6af845-e769-41d0-8ea6-618d5117712a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-25T09:53:35.677Z_

<details><summary>↩ Tool result · `toolu_015kg5fe92NzMjTmgxeBGocD`</summary>

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
  "parentUuid": "24e09f36-811f-4b02-abae-b000bbb1aa6b",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "812b509c-cd60-48fe-a53f-e8f2c7f09544",
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
  "sourceToolAssistantUUID": "24e09f36-811f-4b02-abae-b000bbb1aa6b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 13 · 2026-05-25T09:53:36.164Z_

<details open><summary>🔧 Tool call — Read · `toolu_016Y7HLnuUAuyewDy32JrLqy`</summary>

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
  "parentUuid": "812b509c-cd60-48fe-a53f-e8f2c7f09544",
  "isSidechain": false,
  "requestId": "req_011CbP5o6MHVH7V51dnWgE7v",
  "type": "assistant",
  "uuid": "ec7f8b0d-cd06-4fe6-aba3-7fa66bb8f551",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KCARFsGsQzs2ekeuyj6ZBo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26930,
      "cache_read_input_tokens": 11846,
      "output_tokens": 286,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26930,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 286,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26930,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26930
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

_source line 14 · 2026-05-25T09:53:36.171Z_

<details><summary>↩ Tool result · `toolu_016Y7HLnuUAuyewDy32JrLqy`</summary>

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
  "parentUuid": "ec7f8b0d-cd06-4fe6-aba3-7fa66bb8f551",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "18f2f98e-4966-4bc0-8c6e-22cbe84722dc",
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
  "sourceToolAssistantUUID": "ec7f8b0d-cd06-4fe6-aba3-7fa66bb8f551",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 15 · 2026-05-25T09:53:36.862Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01VA3tVfoUjQ6cmVFqQQuWSt`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "18f2f98e-4966-4bc0-8c6e-22cbe84722dc",
  "isSidechain": false,
  "requestId": "req_011CbP5o6MHVH7V51dnWgE7v",
  "type": "assistant",
  "uuid": "2a6af845-e769-41d0-8ea6-618d5117712a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KCARFsGsQzs2ekeuyj6ZBo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26930,
      "cache_read_input_tokens": 11846,
      "output_tokens": 286,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26930,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 286,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 26930,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26930
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
  "lastPrompt": "项目：contamcal-irt-calibration Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 39 wa…",
  "leafUuid": "78d2a0f1-0ae0-49b1-a463-d6ff20c8f694",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 contamcal-irt-calibration paper audit",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Assistant

_source line 18 · 2026-05-25T09:53:39.629Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read all the .tex files. Let me read them in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "78d2a0f1-0ae0-49b1-a463-d6ff20c8f694",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "7d16269e-0633-4610-9527-e15191466319",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 19 · 2026-05-25T09:53:40.111Z_

审计标准已加载。现在读取所有 .tex 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7d16269e-0633-4610-9527-e15191466319",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "93ad7105-50b7-4597-a49a-253e8074dff8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 20 · 2026-05-25T09:53:41.198Z_

<details open><summary>🔧 Tool call — Read · `toolu_014AbHieGu2uSAZUcyrQuryp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "93ad7105-50b7-4597-a49a-253e8074dff8",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "205828b8-174a-4561-8a5f-d4fd78a7f836",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 21 · 2026-05-25T09:53:41.203Z_

<details><summary>↩ Tool result · `toolu_014AbHieGu2uSAZUcyrQuryp`</summary>

```text
1	Benchmark contamination is widely assumed to inflate language model scores, yet its actual effect has never been measured across model families. We perform controlled supervised fine-tuning (SFT) injection at five dosage levels into six models (7B to 14.7B) from five open-source families and discover a spectrum of dose-response patterns, not uniform inflation. Two patterns replicate across independent families: Immune (Phi-4, LLaMA-3.1) and Benefit (statistically significant for Gemma-2, bootstrap 95\% CI [$+$1.49, $+$3.14]\,pp; borderline for OLMo-2 and Falcon3). Collapse and V-recovery are each observed in one family (Qwen2.5) across three seeds but remain preliminary pending independent replication. Effects are benchmark-conditional: MMLU-targeted contamination improves GSM8K in five of six families, even those harmed on MMLU. Difference-in-differences analysis detects no item-specific memorization; a volume-matched control attributes 45\% of Benefit to data quantity. ContamCal, our diagnostic framework combining multi-signal exposure mapping with contamination-augmented Item Response Theory (IRT), enables domain-level contamination diagnosis with credible intervals, revealing that Social Sciences contamination effects are negative while STEM effects are positive, a pattern invisible to aggregate scoring. Out-of-sample validation on LLaMA-3.1-8B confirms that model family characteristics beyond baseline ability modulate vulnerability. Model-specific dose-response profiling is necessary for reliable benchmark interpretation.
2	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "205828b8-174a-4561-8a5f-d4fd78a7f836",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "1c81b78d-e897-41f0-a89a-f0ab17270478",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/abstract.tex",
      "content": "Benchmark contamination is widely assumed to inflate language model scores, yet its actual effect has never been measured across model families. We perform controlled supervised fine-tuning (SFT) injection at five dosage levels into six models (7B to 14.7B) from five open-source families and discover a spectrum of dose-response patterns, not uniform inflation. Two patterns replicate across independent families: Immune (Phi-4, LLaMA-3.1) and Benefit (statistically significant for Gemma-2, bootstrap 95\\% CI [$+$1.49, $+$3.14]\\,pp; borderline for OLMo-2 and Falcon3). Collapse and V-recovery are each observed in one family (Qwen2.5) across three seeds but remain preliminary pending independent replication. Effects are benchmark-conditional: MMLU-targeted contamination improves GSM8K in five of six families, even those harmed on MMLU. Difference-in-differences analysis detects no item-specific memorization; a volume-matched control attributes 45\\% of Benefit to data quantity. ContamCal, our diagnostic framework combining multi-signal exposure mapping with contamination-augmented Item Response Theory (IRT), enables domain-level contamination diagnosis with credible intervals, revealing that Social Sciences contamination effects are negative while STEM effects are positive, a pattern invisible to aggregate scoring. Out-of-sample validation on LLaMA-3.1-8B confirms that model family characteristics beyond baseline ability modulate vulnerability. Model-specific dose-response profiling is necessary for reliable benchmark interpretation.\n",
      "numLines": 2,
      "startLine": 1,
      "totalLines": 2
    }
  },
  "sourceToolAssistantUUID": "205828b8-174a-4561-8a5f-d4fd78a7f836",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-25T09:53:41.563Z_

<details open><summary>🔧 Tool call — Read · `toolu_01S62KX3FjqErQMLFPJuUkJH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1c81b78d-e897-41f0-a89a-f0ab17270478",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "49a5e6ff-7809-4bc5-b343-f6b040ce5409",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 23 · 2026-05-25T09:53:41.569Z_

<details><summary>↩ Tool result · `toolu_01S62KX3FjqErQMLFPJuUkJH`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Benchmark scores drive model selection and research priorities for large language models (LLMs), yet training data contamination is pervasive: trillion-token web crawls routinely ingest benchmark items \citep{oren2024proving}, and practitioners cannot determine how much of a reported score reflects genuine capability versus memorization \citep{hendrycks2021mmlu,chang2025benchmarking}. Despite twenty mitigation strategies \citep{sun2025emperor}, contamination-free benchmarks \citep{white2024livebench}, and dynamic regeneration \citep{dong_2024_cdd}, a fundamental question remains: what is the actual effect of contamination on aggregate scores? The implicit assumption is uniform inflation, but this has never been tested across model families.
4	
5	We perform controlled supervised fine-tuning (SFT) injection (Low-Rank Adaptation [LoRA], five dosage levels) into six models spanning five independent families from five labs (Alibaba, Microsoft, Allen AI, Google, TII) and discover a spectrum of dose-response patterns (Figure~\ref{fig:dose_response}, Table~\ref{tab:taxonomy}), ranging from immunity (Phi-4, $\pm$0.5pp) and benefit ($+$3--4pp, three families) to collapse (Qwen-14B, $-$9 to $-$25pp across seeds).
6	
7	\begin{figure}[t]
8	\centering
9	\includegraphics[width=\columnwidth]{figures/fig_dose_response.pdf}
10	\caption{MMLU accuracy vs.\ contamination dosage (5-shot, seed$=$42; LLaMA-3.1 at seed$=$0). Immune and Benefit replicate across families; Collapse and V-recovery are preliminary (Qwen2.5-specific). Cross-seed stability in Table~\ref{tab:cross_seed}.}
11	\label{fig:dose_response}
12	\end{figure}
13	
14	Across six models, three lower-baseline models benefit ($+$3.2 to $+$4.2pp), one is immune (Phi-4), and the remaining two (both Qwen2.5) show harm, with the 14B model 5$\times$ more fragile than 7B (Figure~\ref{fig:baseline_vulnerability}). These effects are benchmark-conditional: the same model can collapse on MMLU ($-$9.4pp) yet gain on GSM8K ($+$13pp). ContamCal, our diagnostic framework combining multi-signal exposure mapping with contamination-augmented Item Response Theory (IRT; 2PL+$\gamma_k$), enables this characterization.
15	
16	\begin{table}[t]
17	\centering
18	\caption{Observed dose-response patterns under controlled SFT injection (seed$=$42, MMLU). $\Delta$acc: d000$\to$d100 change (95\% bootstrap CI, $B=10{,}000$). Stab.: fraction of bootstrap resamples ($B=10{,}000$) that yield the same Algorithm~\ref{alg:profile-classification} classification. Classifications are robust to threshold choice (5/5 original families at 100\% stability across 30 $(\tau,\sigma)$ combinations; Appendix~\ref{sec:classification_sensitivity}).}
19	\label{tab:taxonomy}
20	\setlength{\tabcolsep}{2pt}
21	\resizebox{\columnwidth}{!}{%
22	\begin{tabular}{llcccccc}
23	\toprule
24	Pattern & Model & Base & $\Delta$acc & CI & Peak & St. & R. \\
25	\midrule
26	Immune & Phi-4 14.7B & 76.4\% & $\pm$0.5pp & [$-$0.60, $+$0.26] & negl. & 100\% & \checkmark \\
27	Collapse & Qwen-14B & 69.4\% & $-$9.4pp\textsuperscript{$\ddagger$} & [$-$12.74, $-$9.0] & --- & 100\% & $\triangle$ \\
28	V-recovery & Qwen-7B & 66.1\% & $-$1.8pp & [$-$2.36, $-$1.22] & $-$3.1\textsuperscript{d025} & 99.6\% & $\triangle$ \\
29	Benefit & Gemma-2 9B & 61.9\% & $+$3.8pp & [$+$3.18, $+$4.33] & n-mono. & 76.6\% & \checkmark \\
30	Benefit & Falcon3 7B & 58.8\% & $+$4.2pp & [$+$3.60, $+$4.79] & mono. & 96.1\% & \checkmark \\
31	Benefit & OLMo-2 7B & 53.8\% & $+$3.2pp\textsuperscript{$\dagger$} & [$+$2.73, $+$3.71] & sat.\textsuperscript{d050} & 100\% & \checkmark \\
32	\bottomrule
33	\multicolumn{8}{l}{\scriptsize $^{\ddagger}$Cross-seed range $-$9.4 to $-$25.0pp (s42/s123/s0); see Table~\ref{tab:cross_seed}.} \\
34	\multicolumn{8}{l}{\scriptsize $^{\dagger}$Seed-sensitive: s42 $+$3.2pp, s123 $-$0.55pp ($<$1pp threshold), s0 $+$1.4pp; cross-seed CI crosses zero. See \S\ref{sec:cross_seed}.} \\
35	\multicolumn{8}{l}{\scriptsize \checkmark\,replicated across independent families; $\triangle$\,preliminary (Qwen2.5-specific, pending replication).}
36	\end{tabular}}
37	\end{table}
38	
39	Our contributions:
40	\begin{enumerate}
41	    \item \textbf{Dose-response profiles with cross-seed and cross-benchmark validation.} Controlled injection across five families reveals two replicated patterns (Immune, Benefit) and two preliminary Qwen2.5-specific patterns (Collapse, V-recovery). Out-of-sample validation on LLaMA-3.1-8B confirms generalizability. Cross-benchmark transfer reveals directional reversal on GSM8K for three families. Multi-seed evaluation ($n\!=\!3$) shows direction is reproducible but magnitude is seed-sensitive.
42	    \item \textbf{Domain-level contamination diagnosis via IRT.} ContamCal embeds multi-signal Reciprocal Rank Fusion (RRF) exposure scores in a contamination-augmented IRT model (2PL+$\gamma$), applying standard explanatory IRT \citep{deboeck_2004_explanatory_irt} to LLM contamination and enabling domain-level diagnosis with credible intervals. Domain analysis reveals opposing contamination directions (Social Sciences $\gamma_d < 0$, STEM $\gamma_d > 0$) invisible to aggregate scoring. No item-specific memorization is detected via difference-in-differences (minimum detectable effect size [MDES] 1.25--2.05pp).
43	    \item \textbf{Diagnostic pipeline requirements and signal failure.} Min-K\%++ \citep{zhang_2024_minkpp} exhibits directional reversal at 0.5B (paired Cohen's $d = -1.98$ at d100). RRF-based multi-signal fusion is essential: a single-signal pipeline produces severe model misfit (posterior predictive $p$-value [PPP] $< 0.001$). Simulation establishes $\gamma$ recovery requires $J \geq 50$ at area under the curve (AUC) $\geq 0.55$, above current practice ($J = 8$--$30$).
44	\end{enumerate}
45	
46	\noindent Code and data are available.\footnote{\url{https://github.com/anonymous-nlp-2026-2/contamcal-irt-calibration}}
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "49a5e6ff-7809-4bc5-b343-f6b040ce5409",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "a4df8903-9148-4a61-9b9e-ae4518b60627",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\\label{sec:introduction}\n\nBenchmark scores drive model selection and research priorities for large language models (LLMs), yet training data contamination is pervasive: trillion-token web crawls routinely ingest benchmark items \\citep{oren2024proving}, and practitioners cannot determine how much of a reported score reflects genuine capability versus memorization \\citep{hendrycks2021mmlu,chang2025benchmarking}. Despite twenty mitigation strategies \\citep{sun2025emperor}, contamination-free benchmarks \\citep{white2024livebench}, and dynamic regeneration \\citep{dong_2024_cdd}, a fundamental question remains: what is the actual effect of contamination on aggregate scores? The implicit assumption is uniform inflation, but this has never been tested across model families.\n\nWe perform controlled supervised fine-tuning (SFT) injection (Low-Rank Adaptation [LoRA], five dosage levels) into six models spanning five independent families from five labs (Alibaba, Microsoft, Allen AI, Google, TII) and discover a spectrum of dose-response patterns (Figure~\\ref{fig:dose_response}, Table~\\ref{tab:taxonomy}), ranging from immunity (Phi-4, $\\pm$0.5pp) and benefit ($+$3--4pp, three families) to collapse (Qwen-14B, $-$9 to $-$25pp across seeds).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_dose_response.pdf}\n\\caption{MMLU accuracy vs.\\ contamination dosage (5-shot, seed$=$42; LLaMA-3.1 at seed$=$0). Immune and Benefit replicate across families; Collapse and V-recovery are preliminary (Qwen2.5-specific). Cross-seed stability in Table~\\ref{tab:cross_seed}.}\n\\label{fig:dose_response}\n\\end{figure}\n\nAcross six models, three lower-baseline models benefit ($+$3.2 to $+$4.2pp), one is immune (Phi-4), and the remaining two (both Qwen2.5) show harm, with the 14B model 5$\\times$ more fragile than 7B (Figure~\\ref{fig:baseline_vulnerability}). These effects are benchmark-conditional: the same model can collapse on MMLU ($-$9.4pp) yet gain on GSM8K ($+$13pp). ContamCal, our diagnostic framework combining multi-signal exposure mapping with contamination-augmented Item Response Theory (IRT; 2PL+$\\gamma_k$), enables this characterization.\n\n\\begin{table}[t]\n\\centering\n\\caption{Observed dose-response patterns under controlled SFT injection (seed$=$42, MMLU). $\\Delta$acc: d000$\\to$d100 change (95\\% bootstrap CI, $B=10{,}000$). Stab.: fraction of bootstrap resamples ($B=10{,}000$) that yield the same Algorithm~\\ref{alg:profile-classification} classification. Classifications are robust to threshold choice (5/5 original families at 100\\% stability across 30 $(\\tau,\\sigma)$ combinations; Appendix~\\ref{sec:classification_sensitivity}).}\n\\label{tab:taxonomy}\n\\setlength{\\tabcolsep}{2pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccccc}\n\\toprule\nPattern & Model & Base & $\\Delta$acc & CI & Peak & St. & R. \\\\\n\\midrule\nImmune & Phi-4 14.7B & 76.4\\% & $\\pm$0.5pp & [$-$0.60, $+$0.26] & negl. & 100\\% & \\checkmark \\\\\nCollapse & Qwen-14B & 69.4\\% & $-$9.4pp\\textsuperscript{$\\ddagger$} & [$-$12.74, $-$9.0] & --- & 100\\% & $\\triangle$ \\\\\nV-recovery & Qwen-7B & 66.1\\% & $-$1.8pp & [$-$2.36, $-$1.22] & $-$3.1\\textsuperscript{d025} & 99.6\\% & $\\triangle$ \\\\\nBenefit & Gemma-2 9B & 61.9\\% & $+$3.8pp & [$+$3.18, $+$4.33] & n-mono. & 76.6\\% & \\checkmark \\\\\nBenefit & Falcon3 7B & 58.8\\% & $+$4.2pp & [$+$3.60, $+$4.79] & mono. & 96.1\\% & \\checkmark \\\\\nBenefit & OLMo-2 7B & 53.8\\% & $+$3.2pp\\textsuperscript{$\\dagger$} & [$+$2.73, $+$3.71] & sat.\\textsuperscript{d050} & 100\\% & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{8}{l}{\\scriptsize $^{\\ddagger}$Cross-seed range $-$9.4 to $-$25.0pp (s42/s123/s0); see Table~\\ref{tab:cross_seed}.} \\\\\n\\multicolumn{8}{l}{\\scriptsize $^{\\dagger}$Seed-sensitive: s42 $+$3.2pp, s123 $-$0.55pp ($<$1pp threshold), s0 $+$1.4pp; cross-seed CI crosses zero. See \\S\\ref{sec:cross_seed}.} \\\\\n\\multicolumn{8}{l}{\\scriptsize \\checkmark\\,replicated across independent families; $\\triangle$\\,preliminary (Qwen2.5-specific, pending replication).}\n\\end{tabular}}\n\\end{table}\n\nOur contributions:\n\\begin{enumerate}\n    \\item \\textbf{Dose-response profiles with cross-seed and cross-benchmark validation.} Controlled injection across five families reveals two replicated patterns (Immune, Benefit) and two preliminary Qwen2.5-specific patterns (Collapse, V-recovery). Out-of-sample validation on LLaMA-3.1-8B confirms generalizability. Cross-benchmark transfer reveals directional reversal on GSM8K for three families. Multi-seed evaluation ($n\\!=\\!3$) shows direction is reproducible but magnitude is seed-sensitive.\n    \\item \\textbf{Domain-level contamination diagnosis via IRT.} ContamCal embeds multi-signal Reciprocal Rank Fusion (RRF) exposure scores in a contamination-augmented IRT model (2PL+$\\gamma$), applying standard explanatory IRT \\citep{deboeck_2004_explanatory_irt} to LLM contamination and enabling domain-level diagnosis with credible intervals. Domain analysis reveals opposing contamination directions (Social Sciences $\\gamma_d < 0$, STEM $\\gamma_d > 0$) invisible to aggregate scoring. No item-specific memorization is detected via difference-in-differences (minimum detectable effect size [MDES] 1.25--2.05pp).\n    \\item \\textbf{Diagnostic pipeline requirements and signal failure.} Min-K\\%++ \\citep{zhang_2024_minkpp} exhibits directional reversal at 0.5B (paired Cohen's $d = -1.98$ at d100). RRF-based multi-signal fusion is essential: a single-signal pipeline produces severe model misfit (posterior predictive $p$-value [PPP] $< 0.001$). Simulation establishes $\\gamma$ recovery requires $J \\geq 50$ at area under the curve (AUC) $\\geq 0.55$, above current practice ($J = 8$--$30$).\n\\end{enumerate}\n\n\\noindent Code and data are available.\\footnote{\\url{https://github.com/anonymous-nlp-2026-2/contamcal-irt-calibration}}\n",
      "numLines": 47,
      "startLine": 1,
      "totalLines": 47
    }
  },
  "sourceToolAssistantUUID": "49a5e6ff-7809-4bc5-b343-f6b040ce5409",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-25T09:53:42.036Z_

<details open><summary>🔧 Tool call — Read · `toolu_011MyvisbevPFF5L8EsN1Xt3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a4df8903-9148-4a61-9b9e-ae4518b60627",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "de1e00b4-f17e-4346-b6fa-ec339908bcca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 25 · 2026-05-25T09:53:42.040Z_

<details><summary>↩ Tool result · `toolu_011MyvisbevPFF5L8EsN1Xt3`</summary>

```text
1	\section{Related Work}\label{sec:related_work}
2	
3	\begin{figure*}[t]
4	\centering
5	\includegraphics[width=0.95\textwidth]{figures/fig_pipeline.pdf}
6	\caption{ContamCal three-stage pipeline. Stage~1 fuses training-free detection signals into per-item exposure scores via Reciprocal Rank Fusion. Stage~2 embeds these scores in a contamination-augmented 2PL IRT model, recovering clean ability estimates with credible intervals. Stage~3 classifies the resulting dose-response trajectories into canonical patterns.}
7	\label{fig:pipeline}
8	\end{figure*}
9	
10	\paragraph{Contamination detection.}
11	Detection methods flag contaminated items via token-level surprisal \citep{shi_2023_minkprob,zhang_2024_minkpp}, accuracy gaps on paraphrases or rephrased items \citep{dekoninck2024constat,yang2023rethinking}, kernel divergence \citep{choi_2025_kds}, completion probes \citep{dong_2024_cdd,golchin2024time}, and parallel test sets \citep{zhang_2024_gsm1k}; see \citet{chen2025benchmarking,singh2024evaluation,sainz2023nlp} for surveys. \citet{balloccu2024leak} document contamination malpractices in closed-source LLMs; \citet{bordt2025forget} argue that contamination effects are often negligible in practice. Earlier work characterized contamination as memorization \citep{carlini2023quantifying,magar_2022_contamination,li_2024_task_contamination,xu_2024_leakage}; \citet{tao2025detecting} and \citet{kocyigit2025impact} address RL post-training. These methods perform binary classification without quantifying effect sizes.
12	
13	\paragraph{Contamination quantification and mitigation.}
14	On mitigation, \citet{sun2025emperor} find none of twenty approaches reliably restores clean performance; DCR \citep{xu2025dcr} estimates decontaminated scores but without uncertainty quantification. ContamCal consumes detection signals as inputs and produces calibrated ability with credible intervals. Three concurrent lines of work directly address contamination quantification. \citet{han2026quantifying} apply observational differential item functioning (DIF) to detect contamination without controlled dosage, achieving detection but not dose-response profiling. \citet{schaeffer2026causally} perform controlled pretraining-stage injection with larger seed counts ($n\!=\!10$), establishing causal contamination effects at the pretraining level; our $n\!=\!3$ seed design trades statistical power for broader family coverage. Our work complements both: like Schaeffer et al., we use controlled injection for causal identification, but at the SFT stage with precise dosage control; like Han et al., we employ IRT-based modeling, but with ground-truth contamination labels enabling dose-response characterization.
15	
16	\paragraph{IRT for LLM evaluation.}
17	Item Response Theory \citep{lord_1980_irt,hambleton_1991_irt} has gained traction for LLM evaluation \citep{liang_2023_helm}: \citet{rodriguez2021evaluation}, TinyBenchmarks \citep{polo_2024_tinybenchmarks}, Growing Pains \citep{habba_2025_growing_pains}, HiBayES \citep{luettgau_2025_hibayes}, PSN-IRT \citep{zhou_2025_psnirt}; see \citet{lalor_2024_irt_nlp} for a tutorial and \citet{gu2024olmes} for evaluation standardization. Most directly related, \citet{han2026quantifying} apply group-based DIF \citep{holland_1993_dif} to quantify item-level contamination effects. ContamCal differs by using continuous exposure covariates (explanatory DIF; \citealp{deboeck_2004_explanatory_irt}), providing calibrated ability with credible intervals, and domain-level diagnosis ($\gamma_d$); the approaches are complementary (item-level DIF for benchmark curation, model-level calibration for score interpretation). Our $\gamma$ parameter is formally an instance of explanatory DIF \citep{deboeck_2004_explanatory_irt,eckerly_2017_item_compromise}: the contamination covariate differentially affects response probability, analogous to item compromise models in educational measurement \citep{sinharay_2017_preknowledge,holland_1993_dif,camilli_1994_dif,swaminathan_1990_dif}. We use ``calibration'' in the psychometric sense of adjusting scores to approximate uncontaminated performance, distinct from probability calibration \citep{guo_2017_calibration}.
18	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "de1e00b4-f17e-4346-b6fa-ec339908bcca",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "b6be5dd0-d736-4eb1-ad85-5976a023814b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\\label{sec:related_work}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{figures/fig_pipeline.pdf}\n\\caption{ContamCal three-stage pipeline. Stage~1 fuses training-free detection signals into per-item exposure scores via Reciprocal Rank Fusion. Stage~2 embeds these scores in a contamination-augmented 2PL IRT model, recovering clean ability estimates with credible intervals. Stage~3 classifies the resulting dose-response trajectories into canonical patterns.}\n\\label{fig:pipeline}\n\\end{figure*}\n\n\\paragraph{Contamination detection.}\nDetection methods flag contaminated items via token-level surprisal \\citep{shi_2023_minkprob,zhang_2024_minkpp}, accuracy gaps on paraphrases or rephrased items \\citep{dekoninck2024constat,yang2023rethinking}, kernel divergence \\citep{choi_2025_kds}, completion probes \\citep{dong_2024_cdd,golchin2024time}, and parallel test sets \\citep{zhang_2024_gsm1k}; see \\citet{chen2025benchmarking,singh2024evaluation,sainz2023nlp} for surveys. \\citet{balloccu2024leak} document contamination malpractices in closed-source LLMs; \\citet{bordt2025forget} argue that contamination effects are often negligible in practice. Earlier work characterized contamination as memorization \\citep{carlini2023quantifying,magar_2022_contamination,li_2024_task_contamination,xu_2024_leakage}; \\citet{tao2025detecting} and \\citet{kocyigit2025impact} address RL post-training. These methods perform binary classification without quantifying effect sizes.\n\n\\paragraph{Contamination quantification and mitigation.}\nOn mitigation, \\citet{sun2025emperor} find none of twenty approaches reliably restores clean performance; DCR \\citep{xu2025dcr} estimates decontaminated scores but without uncertainty quantification. ContamCal consumes detection signals as inputs and produces calibrated ability with credible intervals. Three concurrent lines of work directly address contamination quantification. \\citet{han2026quantifying} apply observational differential item functioning (DIF) to detect contamination without controlled dosage, achieving detection but not dose-response profiling. \\citet{schaeffer2026causally} perform controlled pretraining-stage injection with larger seed counts ($n\\!=\\!10$), establishing causal contamination effects at the pretraining level; our $n\\!=\\!3$ seed design trades statistical power for broader family coverage. Our work complements both: like Schaeffer et al., we use controlled injection for causal identification, but at the SFT stage with precise dosage control; like Han et al., we employ IRT-based modeling, but with ground-truth contamination labels enabling dose-response characterization.\n\n\\paragraph{IRT for LLM evaluation.}\nItem Response Theory \\citep{lord_1980_irt,hambleton_1991_irt} has gained traction for LLM evaluation \\citep{liang_2023_helm}: \\citet{rodriguez2021evaluation}, TinyBenchmarks \\citep{polo_2024_tinybenchmarks}, Growing Pains \\citep{habba_2025_growing_pains}, HiBayES \\citep{luettgau_2025_hibayes}, PSN-IRT \\citep{zhou_2025_psnirt}; see \\citet{lalor_2024_irt_nlp} for a tutorial and \\citet{gu2024olmes} for evaluation standardization. Most directly related, \\citet{han2026quantifying} apply group-based DIF \\citep{holland_1993_dif} to quantify item-level contamination effects. ContamCal differs by using continuous exposure covariates (explanatory DIF; \\citealp{deboeck_2004_explanatory_irt}), providing calibrated ability with credible intervals, and domain-level diagnosis ($\\gamma_d$); the approaches are complementary (item-level DIF for benchmark curation, model-level calibration for score interpretation). Our $\\gamma$ parameter is formally an instance of explanatory DIF \\citep{deboeck_2004_explanatory_irt,eckerly_2017_item_compromise}: the contamination covariate differentially affects response probability, analogous to item compromise models in educational measurement \\citep{sinharay_2017_preknowledge,holland_1993_dif,camilli_1994_dif,swaminathan_1990_dif}. We use ``calibration'' in the psychometric sense of adjusting scores to approximate uncontaminated performance, distinct from probability calibration \\citep{guo_2017_calibration}.\n",
      "numLines": 18,
      "startLine": 1,
      "totalLines": 18
    }
  },
  "sourceToolAssistantUUID": "de1e00b4-f17e-4346-b6fa-ec339908bcca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-25T09:53:42.585Z_

<details open><summary>🔧 Tool call — Read · `toolu_01T7DjrfUVemxL2tjZ4cisSm`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b6be5dd0-d736-4eb1-ad85-5976a023814b",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "87fd6fcf-bbc3-462c-8fce-eb3d885f2c67",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 27 · 2026-05-25T09:53:42.590Z_

<details><summary>↩ Tool result · `toolu_01T7DjrfUVemxL2tjZ4cisSm`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	ContamCal operates in three stages (Figure~\ref{fig:pipeline}): Stage~1 estimates per-item contamination exposure via training-free signal fusion; Stage~2 embeds these scores in a contamination-augmented IRT model to recover clean ability estimates with credible intervals; Stage~3 classifies dose-response trajectories into canonical patterns.
5	
6	\subsection{Problem Formulation}
7	\label{sec:formulation}
8	
9	Let $y_{ijk} \in \{0,1\}$ denote the binary response of model~$j$ ($j=1,\ldots,J$) to item~$i$ ($i=1,\ldots,I_k$) on benchmark~$k$. Standard IRT assumes $P(y_{ijk}=1) = f(\theta_j, \boldsymbol{\xi}_i)$ where $\theta_j$ is latent ability and $\boldsymbol{\xi}_i$ collects item parameters. When training corpora contain benchmark items, the observed ability $\hat{\theta}_j$ confounds genuine capability with memorization.
10	
11	Our goal is to estimate $\theta_j^{\text{clean}}$, the ability each model would exhibit absent contamination, and to diagnose contamination effects at domain granularity. We adapt item compromise IRT \citep{eckerly_2017_item_compromise,sinharay_2017_preknowledge} and explanatory IRT \citep{deboeck_2004_explanatory_irt} for LLM evaluation: replacing binary leakage indicators with continuous exposure scores $e_{ij} \in [0,1]$, fitting per-benchmark models to handle the shared item pool \citep{de_ayala_2009_irt}, and recovering clean ability via counterfactual inference (setting $e_{ij}=0$).
12	
13	\subsection{Stage 1: Multi-Signal Exposure Mapping}
14	\label{sec:stage1}
15	
16	For each model~$j$ and item~$i$, we consider four candidate detection signals. \textbf{S1}~(Embedding similarity): cosine similarity between the item embedding and its nearest neighbor in the SFT training corpus. \textbf{S2}~(Min-K\%++): a membership inference statistic based on token-level surprisal \citep{zhang_2024_minkpp}. \textbf{S3}~(ConStat): the accuracy gap between original and paraphrased item variants \citep{dekoninck2024constat}. \textbf{S4}~(Self-Critique): negative entropy of model self-evaluation distributions (Appendix~\ref{sec:s4_details}), inspired by the finding that LLMs can assess their own knowledge \citep{kadavath2022}; concurrent work by \citet{tao2025detecting} uses a related but mechanistically distinct entropy collapse approach targeting RL-trained models. S3 requires paired paraphrased items as reference and is therefore limited to benchmarks with existing paraphrase sets. Our primary pipeline uses the remaining three signals ($\mathcal{S} = \{\text{S1, S2, S4}\}$) and applies to any benchmark without auxiliary data. S2 and S4 exhibit known failure modes under RL post-training, which we characterize in \S\ref{sec:signal_failure}. Item-level classification performance of the exposure scores is reported in Appendix~\ref{sec:sij_classification}.
17	
18	We aggregate signals via Reciprocal Rank Fusion \citep[RRF;][]{cormack_2009_rrf}:
19	\begin{equation}
20	\label{eq:rrf}
21	    e_{ij} = \sum_{s \in \mathcal{S}} \frac{1}{\kappa + r_{s}(i)},
22	\end{equation}
23	where $r_s(i)$ is the rank of item~$i$ under signal~$s$ (rank~1 = most suspicious), $\kappa=60$ is the standard RRF smoothing constant, robust to near-random component signals, and $|\mathcal{S}|=3$ in our primary configuration. Raw scores are min-max normalized per model to $e_{ij} \in [0,1]$; the distribution is highly right-skewed (mean 0.041).
24	
25	\subsection{Stage 2: Contamination-Augmented IRT}
26	\label{sec:stage2}
27	
28	\begin{figure}[t]
29	\centering
30	\includegraphics[width=0.92\columnwidth]{figures/fig_baseline_vulnerability.pdf}
31	\caption{Baseline MMLU accuracy vs.\ contamination response at d100 ($N\!=\!6$). Vertical bars show cross-seed range ($n\!=\!2$--$3$ seeds). Shaded band marks the threshold region (61.9--66.1\%) separating Benefit from Harm patterns (observational, not validated; extended in Appendix~\ref{sec:baseline_vs_effect}).}
32	\label{fig:baseline_vulnerability}
33	\end{figure}
34	
35	\paragraph{Primary model: 2PL+$\gamma$.}
36	Our primary specification augments the two-parameter logistic (2PL) model \citep{lord_1980_irt,hambleton_1991_irt} with a contamination covariate. We fit independent IRT models per benchmark~$k$, each with its own contamination effect $\gamma_k$. Per-benchmark fitting avoids cross-benchmark item parameter borrowing while permitting heterogeneous contamination effects. For benchmark~$k$, the response probability is:
37	\begin{equation}
38	\label{eq:2pl_gamma}
39	    P(y_{ijk} = 1) = \sigma\!\bigl(a_i(\theta_j - b_i) + \gamma_k \cdot e_{ij}\bigr),
40	\end{equation}
41	where $\sigma(\cdot)$ is the logistic function, $a_i > 0$ is item discrimination, $b_i \in \mathbb{R}$ is item difficulty, $\theta_j$ is model ability, and $\gamma_k$ is the scalar contamination effect for benchmark~$k$ ($\gamma$ without subscript denotes the pooled effect; $\gamma_d$ denotes per-domain effects, \S\ref{sec:domain_differential}). Each benchmark is fitted independently; when finer-grained diagnosis is needed, we replace $\gamma_k$ with per-domain effects $\gamma_d$ ($d=1,\ldots,D$), fitting Eq.~\eqref{eq:2pl_gamma} separately for each cognitive domain within a benchmark (\S\ref{sec:domain_differential}).
42	
43	We place $\gamma_k$ outside the item discrimination bracket, modeling contamination as a fixed logit shift \citep{de_ayala_2009_irt} rather than the uniform DIF form that would scale contamination effects with item discrimination. A comparison with the uniform DIF alternative ($\gamma$ inside the discrimination bracket) yields equivalent model fit (Appendix~\ref{sec:dif_comparison}). For MC-format benchmarks, a four-parameter logistic (4PL) extension adds guessing and ceiling asymptotes (Appendix~\ref{sec:4pl_details}); this requires $J \geq 16$ and is not used in domain-level analyses ($J = 13$).
44	
45	\paragraph{Inference.}
46	We perform Bayesian inference via the No-U-Turn Sampler (NUTS) \citep{hoffman2014} in Stan \citep{carpenter2017} with four chains and target acceptance 0.95. Priors: $\theta_j \sim \mathcal{N}(0,1)$, $a_i \sim \text{LogNormal}(0, 0.5)$, $b_i \sim \mathcal{N}(0,1)$, $\gamma_k \sim \mathcal{N}(0,1)$. At $J=16$, the $\gamma$ posterior is sensitive to the prior (up to 2.6$\times$ shift across reasonable alternatives; Appendix~\ref{sec:prior_sensitivity}); we therefore treat $\gamma$ estimates as directional indicators rather than precise effect sizes. Convergence requires split-$\hat{R} < 1.01$ and bulk effective sample size (ESS)~$> 400$ for all parameters. Model fit is assessed via the posterior predictive $p$-value (PPP), where values near 0.5 indicate adequate fit.
47	
48	\paragraph{Calibrated score.}
49	The decontaminated accuracy for model~$j$ on benchmark~$k$ is the posterior expectation under zero exposure:
50	\begin{equation}
51	\label{eq:calibrated}
52	    \text{Acc}_{j}^{\text{cal}} = \frac{1}{I_k} \sum_{i=1}^{I_k}\, \mathbb{E}_{\boldsymbol{\psi} \sim p(\boldsymbol{\psi} \mid \mathbf{y})} \!\left[\sigma\!\bigl(a_i(\theta_j - b_i)\bigr)\right],
53	\end{equation}
54	with credible intervals from posterior quantiles. In practice, we average $\sigma(a_i(\theta_j - b_i))$ over posterior draws with $e_{ij}=0$; the spread of draws yields the credible interval. Models with noisier exposure signals receive wider intervals by construction.
55	
56	\paragraph{Identifiability.}
57	\label{sec:fisher}
58	\label{sec:value_decomposition}
59	The reliability of $\gamma$ depends on signal AUC and ensemble size $J$; simulation validates that recovery requires AUC$\geq$0.55 with $J \geq 50$ (Appendix~\ref{sec:identifiability_appendix}; data-generating process (DGP) robustness in Appendix~\ref{sec:threshold_dgp}). Empirically, exposure scores $e_{ij}$ and item difficulty $b_i$ are near-orthogonal (Pearson $|r|<0.13$, $R^2<0.014$ across benchmarks), so $\gamma$ is identified from dosage-induced variation rather than confounded with difficulty. Eq.~\eqref{eq:calibrated} depends on $\theta_j$, not $\gamma$ directly, predicting that vanilla 2PL ($\gamma\!=\!0$) achieves comparable calibration to 2PL+$\gamma$, with $\gamma_k$ serving diagnosis rather than calibration (\S\ref{sec:calibration_results}).
60	
61	\subsection{Dose-Response Profile Classification}
62	\label{sec:classification}
63	
64	Independent of the IRT calibration pipeline, we classify dose-response profiles via a deterministic decision tree (Algorithm~\ref{alg:profile-classification} in Appendix~\ref{sec:classification_algorithm}) parameterized by noise threshold $\tau{=}2$\,pp and severity threshold $\sigma{=}5$\,pp, drawing on pharmacological dose-response modeling \citep{hill1910aggregation,ritz2015dose}. The tree branches on the end-to-end accuracy shift $\Delta{=}a_{100}{-}a_0$, mid-dosage minimum, and maximum mid-trajectory deviation to assign one of four patterns: \textsc{Immune}, \textsc{Collapse}, \textsc{V-recovery}, or \textsc{Benefit}. All thresholds are explicit and adjustable; a 30-combination $(\tau, \sigma)$ grid sweep confirms all families are stable (180/180 pairs; Appendix~\ref{sec:classification_sensitivity}). Family-level classification uses \emph{direction} as the primary criterion (\S\ref{sec:cross_seed}): Immune if the bootstrap CI of the cross-seed mean $\Delta$(d100) includes zero and $|\text{mean}~\Delta| < \tau$; Borderline if the CI includes zero but $|\text{mean}~\Delta| \geq \tau$; otherwise Harm/Benefit by sign. Parametric model selection (Appendix~\ref{sec:parametric_dr}) confirms these classifications for extreme effects but lacks power at $n\!=\!3$ seeds, motivating the rule-based approach.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "87fd6fcf-bbc3-462c-8fce-eb3d885f2c67",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "adf1f972-ab19-40b1-885d-e0c8f6f498fe",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\nContamCal operates in three stages (Figure~\\ref{fig:pipeline}): Stage~1 estimates per-item contamination exposure via training-free signal fusion; Stage~2 embeds these scores in a contamination-augmented IRT model to recover clean ability estimates with credible intervals; Stage~3 classifies dose-response trajectories into canonical patterns.\n\n\\subsection{Problem Formulation}\n\\label{sec:formulation}\n\nLet $y_{ijk} \\in \\{0,1\\}$ denote the binary response of model~$j$ ($j=1,\\ldots,J$) to item~$i$ ($i=1,\\ldots,I_k$) on benchmark~$k$. Standard IRT assumes $P(y_{ijk}=1) = f(\\theta_j, \\boldsymbol{\\xi}_i)$ where $\\theta_j$ is latent ability and $\\boldsymbol{\\xi}_i$ collects item parameters. When training corpora contain benchmark items, the observed ability $\\hat{\\theta}_j$ confounds genuine capability with memorization.\n\nOur goal is to estimate $\\theta_j^{\\text{clean}}$, the ability each model would exhibit absent contamination, and to diagnose contamination effects at domain granularity. We adapt item compromise IRT \\citep{eckerly_2017_item_compromise,sinharay_2017_preknowledge} and explanatory IRT \\citep{deboeck_2004_explanatory_irt} for LLM evaluation: replacing binary leakage indicators with continuous exposure scores $e_{ij} \\in [0,1]$, fitting per-benchmark models to handle the shared item pool \\citep{de_ayala_2009_irt}, and recovering clean ability via counterfactual inference (setting $e_{ij}=0$).\n\n\\subsection{Stage 1: Multi-Signal Exposure Mapping}\n\\label{sec:stage1}\n\nFor each model~$j$ and item~$i$, we consider four candidate detection signals. \\textbf{S1}~(Embedding similarity): cosine similarity between the item embedding and its nearest neighbor in the SFT training corpus. \\textbf{S2}~(Min-K\\%++): a membership inference statistic based on token-level surprisal \\citep{zhang_2024_minkpp}. \\textbf{S3}~(ConStat): the accuracy gap between original and paraphrased item variants \\citep{dekoninck2024constat}. \\textbf{S4}~(Self-Critique): negative entropy of model self-evaluation distributions (Appendix~\\ref{sec:s4_details}), inspired by the finding that LLMs can assess their own knowledge \\citep{kadavath2022}; concurrent work by \\citet{tao2025detecting} uses a related but mechanistically distinct entropy collapse approach targeting RL-trained models. S3 requires paired paraphrased items as reference and is therefore limited to benchmarks with existing paraphrase sets. Our primary pipeline uses the remaining three signals ($\\mathcal{S} = \\{\\text{S1, S2, S4}\\}$) and applies to any benchmark without auxiliary data. S2 and S4 exhibit known failure modes under RL post-training, which we characterize in \\S\\ref{sec:signal_failure}. Item-level classification performance of the exposure scores is reported in Appendix~\\ref{sec:sij_classification}.\n\nWe aggregate signals via Reciprocal Rank Fusion \\citep[RRF;][]{cormack_2009_rrf}:\n\\begin{equation}\n\\label{eq:rrf}\n    e_{ij} = \\sum_{s \\in \\mathcal{S}} \\frac{1}{\\kappa + r_{s}(i)},\n\\end{equation}\nwhere $r_s(i)$ is the rank of item~$i$ under signal~$s$ (rank~1 = most suspicious), $\\kappa=60$ is the standard RRF smoothing constant, robust to near-random component signals, and $|\\mathcal{S}|=3$ in our primary configuration. Raw scores are min-max normalized per model to $e_{ij} \\in [0,1]$; the distribution is highly right-skewed (mean 0.041).\n\n\\subsection{Stage 2: Contamination-Augmented IRT}\n\\label{sec:stage2}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.92\\columnwidth]{figures/fig_baseline_vulnerability.pdf}\n\\caption{Baseline MMLU accuracy vs.\\ contamination response at d100 ($N\\!=\\!6$). Vertical bars show cross-seed range ($n\\!=\\!2$--$3$ seeds). Shaded band marks the threshold region (61.9--66.1\\%) separating Benefit from Harm patterns (observational, not validated; extended in Appendix~\\ref{sec:baseline_vs_effect}).}\n\\label{fig:baseline_vulnerability}\n\\end{figure}\n\n\\paragraph{Primary model: 2PL+$\\gamma$.}\nOur primary specification augments the two-parameter logistic (2PL) model \\citep{lord_1980_irt,hambleton_1991_irt} with a contamination covariate. We fit independent IRT models per benchmark~$k$, each with its own contamination effect $\\gamma_k$. Per-benchmark fitting avoids cross-benchmark item parameter borrowing while permitting heterogeneous contamination effects. For benchmark~$k$, the response probability is:\n\\begin{equation}\n\\label{eq:2pl_gamma}\n    P(y_{ijk} = 1) = \\sigma\\!\\bigl(a_i(\\theta_j - b_i) + \\gamma_k \\cdot e_{ij}\\bigr),\n\\end{equation}\nwhere $\\sigma(\\cdot)$ is the logistic function, $a_i > 0$ is item discrimination, $b_i \\in \\mathbb{R}$ is item difficulty, $\\theta_j$ is model ability, and $\\gamma_k$ is the scalar contamination effect for benchmark~$k$ ($\\gamma$ without subscript denotes the pooled effect; $\\gamma_d$ denotes per-domain effects, \\S\\ref{sec:domain_differential}). Each benchmark is fitted independently; when finer-grained diagnosis is needed, we replace $\\gamma_k$ with per-domain effects $\\gamma_d$ ($d=1,\\ldots,D$), fitting Eq.~\\eqref{eq:2pl_gamma} separately for each cognitive domain within a benchmark (\\S\\ref{sec:domain_differential}).\n\nWe place $\\gamma_k$ outside the item discrimination bracket, modeling contamination as a fixed logit shift \\citep{de_ayala_2009_irt} rather than the uniform DIF form that would scale contamination effects with item discrimination. A comparison with the uniform DIF alternative ($\\gamma$ inside the discrimination bracket) yields equivalent model fit (Appendix~\\ref{sec:dif_comparison}). For MC-format benchmarks, a four-parameter logistic (4PL) extension adds guessing and ceiling asymptotes (Appendix~\\ref{sec:4pl_details}); this requires $J \\geq 16$ and is not used in domain-level analyses ($J = 13$).\n\n\\paragraph{Inference.}\nWe perform Bayesian inference via the No-U-Turn Sampler (NUTS) \\citep{hoffman2014} in Stan \\citep{carpenter2017} with four chains and target acceptance 0.95. Priors: $\\theta_j \\sim \\mathcal{N}(0,1)$, $a_i \\sim \\text{LogNormal}(0, 0.5)$, $b_i \\sim \\mathcal{N}(0,1)$, $\\gamma_k \\sim \\mathcal{N}(0,1)$. At $J=16$, the $\\gamma$ posterior is sensitive to the prior (up to 2.6$\\times$ shift across reasonable alternatives; Appendix~\\ref{sec:prior_sensitivity}); we therefore treat $\\gamma$ estimates as directional indicators rather than precise effect sizes. Convergence requires split-$\\hat{R} < 1.01$ and bulk effective sample size (ESS)~$> 400$ for all parameters. Model fit is assessed via the posterior predictive $p$-value (PPP), where values near 0.5 indicate adequate fit.\n\n\\paragraph{Calibrated score.}\nThe decontaminated accuracy for model~$j$ on benchmark~$k$ is the posterior expectation under zero exposure:\n\\begin{equation}\n\\label{eq:calibrated}\n    \\text{Acc}_{j}^{\\text{cal}} = \\frac{1}{I_k} \\sum_{i=1}^{I_k}\\, \\mathbb{E}_{\\boldsymbol{\\psi} \\sim p(\\boldsymbol{\\psi} \\mid \\mathbf{y})} \\!\\left[\\sigma\\!\\bigl(a_i(\\theta_j - b_i)\\bigr)\\right],\n\\end{equation}\nwith credible intervals from posterior quantiles. In practice, we average $\\sigma(a_i(\\theta_j - b_i))$ over posterior draws with $e_{ij}=0$; the spread of draws yields the credible interval. Models with noisier exposure signals receive wider intervals by construction.\n\n\\paragraph{Identifiability.}\n\\label{sec:fisher}\n\\label{sec:value_decomposition}\nThe reliability of $\\gamma$ depends on signal AUC and ensemble size $J$; simulation validates that recovery requires AUC$\\geq$0.55 with $J \\geq 50$ (Appendix~\\ref{sec:identifiability_appendix}; data-generating process (DGP) robustness in Appendix~\\ref{sec:threshold_dgp}). Empirically, exposure scores $e_{ij}$ and item difficulty $b_i$ are near-orthogonal (Pearson $|r|<0.13$, $R^2<0.014$ across benchmarks), so $\\gamma$ is identified from dosage-induced variation rather than confounded with difficulty. Eq.~\\eqref{eq:calibrated} depends on $\\theta_j$, not $\\gamma$ directly, predicting that vanilla 2PL ($\\gamma\\!=\\!0$) achieves comparable calibration to 2PL+$\\gamma$, with $\\gamma_k$ serving diagnosis rather than calibration (\\S\\ref{sec:calibration_results}).\n\n\\subsection{Dose-Response Profile Classification}\n\\label{sec:classification}\n\nIndependent of the IRT calibration pipeline, we classify dose-response profiles via a deterministic decision tree (Algorithm~\\ref{alg:profile-classification} in Appendix~\\ref{sec:classification_algorithm}) parameterized by noise threshold $\\tau{=}2$\\,pp and severity threshold $\\sigma{=}5$\\,pp, drawing on pharmacological dose-response modeling \\citep{hill1910aggregation,ritz2015dose}. The tree branches on the end-to-end accuracy shift $\\Delta{=}a_{100}{-}a_0$, mid-dosage minimum, and maximum mid-trajectory deviation to assign one of four patterns: \\textsc{Immune}, \\textsc{Collapse}, \\textsc{V-recovery}, or \\textsc{Benefit}. All thresholds are explicit and adjustable; a 30-combination $(\\tau, \\sigma)$ grid sweep confirms all families are stable (180/180 pairs; Appendix~\\ref{sec:classification_sensitivity}). Family-level classification uses \\emph{direction} as the primary criterion (\\S\\ref{sec:cross_seed}): Immune if the bootstrap CI of the cross-seed mean $\\Delta$(d100) includes zero and $|\\text{mean}~\\Delta| < \\tau$; Borderline if the CI includes zero but $|\\text{mean}~\\Delta| \\geq \\tau$; otherwise Harm/Benefit by sign. Parametric model selection (Appendix~\\ref{sec:parametric_dr}) confirms these classifications for extreme effects but lacks power at $n\\!=\\!3$ seeds, motivating the rule-based approach.",
      "numLines": 64,
      "startLine": 1,
      "totalLines": 64
    }
  },
  "sourceToolAssistantUUID": "87fd6fcf-bbc3-462c-8fce-eb3d885f2c67",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-25T09:53:43.134Z_

<details open><summary>🔧 Tool call — Read · `toolu_0152kj7zJoiZXTrdvs1pFKW5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/experimental_setup.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "adf1f972-ab19-40b1-885d-e0c8f6f498fe",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "0a0e3aa2-3e0e-461a-8316-cad0807605bd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 29 · 2026-05-25T09:53:43.139Z_

<details><summary>↩ Tool result · `toolu_0152kj7zJoiZXTrdvs1pFKW5`</summary>

```text
1	\section{Experimental Setup}
2	\label{sec:experiments}
3	
4	\subsection{Controlled SFT Injection}
5	\label{sec:injection}
6	
7	We construct a controlled contamination testbed spanning five independent model families from five labs, trained on independent corpora with distinct pre-training recipes: Qwen2.5 \citep{qwen2024qwen25} (0.5B, 1.5B, 3B, 7B, 14B), Phi-4 \citep{abdin2024phi4} (14.7B), OLMo-2 \citep{olmo2team2025} (7B), Gemma-2 \citep{gemmateam2024gemma2} (9B), and Falcon3 \citep{tiiuae2024falcon3} (7B). All models are fine-tuned with a unified LoRA configuration \citep{hu2022lora} ($r=16$, $\alpha=32$, dropout$=0$, targeting all attention and multilayer perceptron (MLP) projections; lr$=5\times10^{-5}$, bf16, 1 epoch, batch size$=1$, gradient accumulation$=16$, warmup ratio$=0.03$; trainable parameters range from 0.45\% of Phi-4 14.7B to 2.10\% of Qwen2.5-0.5B; convergence in Appendix~\ref{sec:training_convergence}) on a general-purpose SFT corpus into which benchmark items are injected at five dosage levels: d000 (0\%, clean control), d005 (5\%), d025 (25\%), d050 (50\%), and d100 (100\%). Contaminated items augment (not replace) the base SFT corpus, yielding 50.0k (d000), 50.8k (d005), 54.1k (d025), 58.3k (d050), and 66.5k (d100) total training examples ($+$33\% volume at d100 vs.\ d000).
8	
9	Qwen2.5 serves as the primary within-family series (five scale points, 0.5B--14B). Models at $\leq$3B are trained with two seeds at four dosage levels; 7B and 14B at all five dosages. The four cross-family models are each trained at five dosages with a single seed, serving as consistency checks rather than independent confirmatory analyses. This yields over 55 checkpoints spanning nine sizes across five families. We exclude 0.5B from multiple-choice (MC) IRT due to position bias (A-option rate: 46\% at d000 to 98\% at d100; \S\ref{sec:signal_failure}; details in Appendix~\ref{sec:exclusion_details}). We additionally validate our dose-response profiles on a held-out sixth family, LLaMA-3.1-8B \citep{grattafiori2024llama3} (Meta), which was not used during profile construction. LLaMA-3.1 is trained at three dosage levels (d000, d025, d100) to verify that Algorithm~\ref{alg:profile-classification} generalizes to unseen model families.
10	
11	\subsection{Benchmarks, Domains, and Evaluation}
12	\label{sec:benchmarks}
13	
14	We evaluate on three benchmarks spanning distinct cognitive demands and response formats.
15	
16	\textbf{MMLU} \citep{hendrycks2021mmlu} (5-shot): 14,042 multiple-choice items across 57 subjects, grouped into 8 cognitive domains (Math, Science, CS \& Engineering, Medical, Humanities, Social Sciences, Business \& Law, Other). This stratification reveals within-benchmark heterogeneity that aggregate scoring obscures (\S\ref{sec:results}).
17	
18	\textbf{ARC-Challenge} \citep{clark2018arc} (25-shot): 1,172 multiple-choice science reasoning items.
19	
20	\textbf{GSM8K} \citep{cobbe2021gsm8k}: 1,319 open-ended math problems whose free-form generation format avoids multiple-choice artifacts. Gemma-2 is excluded from GSM8K cross-benchmark analysis because MC-format SFT destroys its chain-of-thought (CoT) reasoning: the d000 baseline drops to 17.8\% (vs.\ 73--84\% for other families), indicating CoT collapse rather than a contamination effect.
21	
22	All multiple-choice evaluations use logprob-based scoring under an aligned instruction-template format with fixed few-shot counts; all 75 model--dosage configurations are evaluated under this identical protocol.
23	
24	We assess calibration quality via mean absolute error (MAE) (calibrated vs.\ ground-truth clean accuracy), Kendall $\tau$ (rank preservation), credible interval coverage, posterior predictive $p$-value (PPP), $\gamma$ direction ($P(\gamma\!<\!0 \mid \text{data})$), and split-$\hat{R}$ convergence.
25	
26	\subsection{Baselines}
27	\label{sec:baselines}
28	
29	We compare against seven baselines (Table~\ref{tab:baselines}): \textbf{B0-Raw} (no adjustment), \textbf{B1-Remove\&Rescore} (drop flagged items; B1b uses RRF-filtered items), \textbf{B2-Single2PL+$\gamma$} (aggregate $\gamma$ without domain stratification), \textbf{B3-Vanilla2PL} ($\gamma=0$, isolating IRT ability estimation), \textbf{B4-LinearRegression} (residuals on exposure scores), \textbf{B5-Emperor} (mitigation strategies from \citet{sun2025emperor}; B5b uses the best-performing variant), and \textbf{B6-DCR} (our reimplementation following \citealp{xu2025dcr}).
30	
31	\begin{table}[t]
32	\centering
33	\caption{MMLU method comparison on 300 randomly subsampled items (Qwen2.5, $J$=16). ARC and GSM8K baselines in Appendix~\ref{sec:full_baselines}; ARC IRT diagnostics in Appendix~\ref{sec:arc_irt}.}
34	\label{tab:baselines}
35	\footnotesize
36	\begin{tabular}{lcc}
37	\toprule
38	Method & MAE & $\tau$ \\
39	\midrule
40	B0: Raw Accuracy & \textbf{0.006} & 0.767 \\
41	B1b: Remove \& Rescore & 0.026 & \underline{0.783} \\
42	B3: Vanilla 2PL & 0.008 & 0.731 \\
43	B4: Linear Regression & 0.010 & 0.751 \\
44	B5b: Emperor & \textbf{0.006} & \textbf{0.789} \\
45	B6: DCR (reimpl.) & 0.108 & 0.654 \\
46	ContamCal (2PL+$\gamma$) & 0.009 & 0.731 \\
47	\bottomrule
48	\end{tabular}
49	\end{table}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0a0e3aa2-3e0e-461a-8316-cad0807605bd",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "f07cf282-583e-4b52-9d3a-70cb60eae0d6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/experimental_setup.tex",
      "content": "\\section{Experimental Setup}\n\\label{sec:experiments}\n\n\\subsection{Controlled SFT Injection}\n\\label{sec:injection}\n\nWe construct a controlled contamination testbed spanning five independent model families from five labs, trained on independent corpora with distinct pre-training recipes: Qwen2.5 \\citep{qwen2024qwen25} (0.5B, 1.5B, 3B, 7B, 14B), Phi-4 \\citep{abdin2024phi4} (14.7B), OLMo-2 \\citep{olmo2team2025} (7B), Gemma-2 \\citep{gemmateam2024gemma2} (9B), and Falcon3 \\citep{tiiuae2024falcon3} (7B). All models are fine-tuned with a unified LoRA configuration \\citep{hu2022lora} ($r=16$, $\\alpha=32$, dropout$=0$, targeting all attention and multilayer perceptron (MLP) projections; lr$=5\\times10^{-5}$, bf16, 1 epoch, batch size$=1$, gradient accumulation$=16$, warmup ratio$=0.03$; trainable parameters range from 0.45\\% of Phi-4 14.7B to 2.10\\% of Qwen2.5-0.5B; convergence in Appendix~\\ref{sec:training_convergence}) on a general-purpose SFT corpus into which benchmark items are injected at five dosage levels: d000 (0\\%, clean control), d005 (5\\%), d025 (25\\%), d050 (50\\%), and d100 (100\\%). Contaminated items augment (not replace) the base SFT corpus, yielding 50.0k (d000), 50.8k (d005), 54.1k (d025), 58.3k (d050), and 66.5k (d100) total training examples ($+$33\\% volume at d100 vs.\\ d000).\n\nQwen2.5 serves as the primary within-family series (five scale points, 0.5B--14B). Models at $\\leq$3B are trained with two seeds at four dosage levels; 7B and 14B at all five dosages. The four cross-family models are each trained at five dosages with a single seed, serving as consistency checks rather than independent confirmatory analyses. This yields over 55 checkpoints spanning nine sizes across five families. We exclude 0.5B from multiple-choice (MC) IRT due to position bias (A-option rate: 46\\% at d000 to 98\\% at d100; \\S\\ref{sec:signal_failure}; details in Appendix~\\ref{sec:exclusion_details}). We additionally validate our dose-response profiles on a held-out sixth family, LLaMA-3.1-8B \\citep{grattafiori2024llama3} (Meta), which was not used during profile construction. LLaMA-3.1 is trained at three dosage levels (d000, d025, d100) to verify that Algorithm~\\ref{alg:profile-classification} generalizes to unseen model families.\n\n\\subsection{Benchmarks, Domains, and Evaluation}\n\\label{sec:benchmarks}\n\nWe evaluate on three benchmarks spanning distinct cognitive demands and response formats.\n\n\\textbf{MMLU} \\citep{hendrycks2021mmlu} (5-shot): 14,042 multiple-choice items across 57 subjects, grouped into 8 cognitive domains (Math, Science, CS \\& Engineering, Medical, Humanities, Social Sciences, Business \\& Law, Other). This stratification reveals within-benchmark heterogeneity that aggregate scoring obscures (\\S\\ref{sec:results}).\n\n\\textbf{ARC-Challenge} \\citep{clark2018arc} (25-shot): 1,172 multiple-choice science reasoning items.\n\n\\textbf{GSM8K} \\citep{cobbe2021gsm8k}: 1,319 open-ended math problems whose free-form generation format avoids multiple-choice artifacts. Gemma-2 is excluded from GSM8K cross-benchmark analysis because MC-format SFT destroys its chain-of-thought (CoT) reasoning: the d000 baseline drops to 17.8\\% (vs.\\ 73--84\\% for other families), indicating CoT collapse rather than a contamination effect.\n\nAll multiple-choice evaluations use logprob-based scoring under an aligned instruction-template format with fixed few-shot counts; all 75 model--dosage configurations are evaluated under this identical protocol.\n\nWe assess calibration quality via mean absolute error (MAE) (calibrated vs.\\ ground-truth clean accuracy), Kendall $\\tau$ (rank preservation), credible interval coverage, posterior predictive $p$-value (PPP), $\\gamma$ direction ($P(\\gamma\\!<\\!0 \\mid \\text{data})$), and split-$\\hat{R}$ convergence.\n\n\\subsection{Baselines}\n\\label{sec:baselines}\n\nWe compare against seven baselines (Table~\\ref{tab:baselines}): \\textbf{B0-Raw} (no adjustment), \\textbf{B1-Remove\\&Rescore} (drop flagged items; B1b uses RRF-filtered items), \\textbf{B2-Single2PL+$\\gamma$} (aggregate $\\gamma$ without domain stratification), \\textbf{B3-Vanilla2PL} ($\\gamma=0$, isolating IRT ability estimation), \\textbf{B4-LinearRegression} (residuals on exposure scores), \\textbf{B5-Emperor} (mitigation strategies from \\citet{sun2025emperor}; B5b uses the best-performing variant), and \\textbf{B6-DCR} (our reimplementation following \\citealp{xu2025dcr}).\n\n\\begin{table}[t]\n\\centering\n\\caption{MMLU method comparison on 300 randomly subsampled items (Qwen2.5, $J$=16). ARC and GSM8K baselines in Appendix~\\ref{sec:full_baselines}; ARC IRT diagnostics in Appendix~\\ref{sec:arc_irt}.}\n\\label{tab:baselines}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nMethod & MAE & $\\tau$ \\\\\n\\midrule\nB0: Raw Accuracy & \\textbf{0.006} & 0.767 \\\\\nB1b: Remove \\& Rescore & 0.026 & \\underline{0.783} \\\\\nB3: Vanilla 2PL & 0.008 & 0.731 \\\\\nB4: Linear Regression & 0.010 & 0.751 \\\\\nB5b: Emperor & \\textbf{0.006} & \\textbf{0.789} \\\\\nB6: DCR (reimpl.) & 0.108 & 0.654 \\\\\nContamCal (2PL+$\\gamma$) & 0.009 & 0.731 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
      "numLines": 49,
      "startLine": 1,
      "totalLines": 49
    }
  },
  "sourceToolAssistantUUID": "0a0e3aa2-3e0e-461a-8316-cad0807605bd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-25T09:53:44.043Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WzeUnAC99aJS9mFULJCMm6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f07cf282-583e-4b52-9d3a-70cb60eae0d6",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "3ad81b3e-442f-485c-9e52-a88f2e12b04a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 31 · 2026-05-25T09:53:44.048Z_

<details><summary>↩ Tool result · `toolu_01WzeUnAC99aJS9mFULJCMm6`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	\begin{figure}[t]
5	\centering
6	\includegraphics[width=0.88\columnwidth]{figures/fig_cross_benchmark_heatmap.pdf}
7	\caption{Cross-benchmark transfer at d100. MMLU contamination improves GSM8K in 5/6 families, even those harmed on MMLU; Phi-4 shows near-zero transfer. Gemma-2 GSM8K ($+$1.33pp) is based on a low baseline (17.8\%, CoT collapse under MC-format SFT) and is excluded from Table~\ref{tab:gsm8k_transfer}.}
8	\label{fig:cross_benchmark_heatmap}
9	\end{figure}
10	
11	Cross-family SFT-injection results (\S\ref{sec:taxonomy}) use seed$=$42 data across six models from five independent families ($\leq$3B dose-response in Appendix~\ref{sec:dose_response_details}). Within-family IRT analyses (\S\ref{sec:calibration_results}--\ref{sec:domain_differential}) use $J=16$ Qwen2.5 models (8$\times$1.5B + 8$\times$3B); domain-level contamination estimates $\gamma_d$ (\S\ref{sec:domain_differential}) are reported at $J=16$ in the text and $J=13$ in Figure~\ref{fig:domain_gamma}.
12	
13	\subsection{Dose-Response Patterns}
14	\label{sec:taxonomy}
15	
16	Applying Algorithm~\ref{alg:profile-classification} to seed$=$42 accuracy trajectories yields a spectrum of dose-response patterns (Table~\ref{tab:taxonomy}, Figure~\ref{fig:dose_response}), not a uniform inflation effect. Figure~\ref{fig:baseline_vulnerability} visualizes how contamination response correlates with baseline accuracy across families.
17	
18	\paragraph{Replication status.}
19	Two patterns replicate across independent families (Table~\ref{tab:taxonomy}). \textit{Immune}: Phi-4 ($\pm$0.5pp), confirmed out-of-sample by LLaMA-3.1 ($-$0.69pp). \textit{Benefit}: three families gain $+$3.2 to $+$4.2pp (Gemma-2, Falcon3, OLMo-2 borderline; \S\ref{sec:cross_seed}). Two patterns are Qwen2.5-specific and await independent replication: Qwen-14B \textit{collapses} ($-$9.4 to $-$25.0pp across seeds) while Qwen-7B shows \textit{V-recovery}. ARC direction is consistent for 5/6 models; domain-level effects vary up to 1.8$\times$ (Appendices~\ref{sec:arc_cross_benchmark},~\ref{sec:domain_decomposition}).
20	
21	\paragraph{Out-of-sample~validation.}
22	LLaMA-3.1-8B (Meta; d000, d025, d100) is classified Immune on both MMLU ($-$0.69pp) and ARC ($+$0.09pp), despite matching OLMo-2's Benefit baseline (53.5\% vs.\ 53.8\%), indicating that family-level factors beyond baseline ability modulate vulnerability. LLaMA-3.1 also shows the strongest GSM8K transfer ($+$16.4pp; Appendix~\ref{sec:gsm8k_dose_response}): target-benchmark immunity does not imply transfer immunity.
23	
24	\subsection{Cross-Benchmark Transfer}
25	\label{sec:gsm8k_transfer}
26	
27	\begin{table}[t]
28	\centering
29	\caption{Cross-benchmark transfer: MMLU vs.\ GSM8K accuracy change at d100. LLaMA-3.1 shows the strongest asymmetric transfer ($+$16.4pp GSM8K despite MMLU immunity). Gemma-2 excluded due to CoT collapse under MC-format SFT.}
30	\label{tab:gsm8k_transfer}
31	\footnotesize
32	\resizebox{\columnwidth}{!}{%
33	\begin{tabular}{lcccl}
34	\toprule
35	Model & MMLU $\Delta$ & GSM8K $\Delta$ & Range & Transfer \\
36	\midrule
37	Phi-4 14.7B & $\pm$0.5pp & $-$0.5pp$^{\diamond}$ & --- & Null \\
38	OLMo-2 7B & $+$3.2pp & $+$2.1pp$^{\S}$ & --- & Consistent \\
39	Falcon3 7B & $+$4.2pp & $+$1.3pp & --- & Consistent \\
40	Qwen-7B & $-$1.8pp & $+$9.4pp & $\pm$0.9 & Reversal \\
41	Qwen-14B & $-$9.4pp & $+$13.1pp & $\pm$7.4 & Reversal$^{\dagger}$ \\
42	LLaMA-3.1 8B & $-$0.7pp & $+$16.4pp$^{\ddagger}$ & --- & Asymmetric \\
43	\bottomrule
44	\multicolumn{5}{l}{\scriptsize $^{\dagger}$d000 baseline seed-sensitive (s42$=$60.8\% vs.\ s123$=$76.7\%); d100 stable ($82\pm0.5$\%).} \\
45	\multicolumn{5}{l}{\scriptsize $^{\S}$Mean of s42 and s123: $+$2.1pp (s42: $+$1.7pp, s123: $+$2.4pp); s0 excluded ($+$9.2pp outlier).} \\
46	\multicolumn{5}{l}{\scriptsize $^{\ddagger}$Single seed (s0); MMLU Immune but strongest GSM8K transfer across all families.} \\
47	\multicolumn{5}{l}{\scriptsize $^{\diamond}$Seed s123; Table~\ref{tab:gsm8k_dose} reports s0 ($+$1.14pp).}
48	\end{tabular}}
49	\end{table}
50	
51	Contamination patterns are a property of the (model, benchmark) pair, not the model alone. Within-MC direction agreement is 86\% (6/7 models; Appendix~\ref{sec:arc_cross_benchmark}); across formats (MC$\to$generative math), agreement drops to 50\% with three families reversing on GSM8K \citep{cobbe2021gsm8k} (Table~\ref{tab:gsm8k_transfer}). Qwen-14B ($-$9.4pp MMLU) gains $+$13.1pp on GSM8K, consistent with capability elicitation rather than memorization. Volume effects are ruled out: d005 ($+$1.5\% data, seed$=$42) already yields $+$6.4pp GSM8K transfer for Qwen-7B.
52	
53	\subsection{Cross-Seed Stability}
54	\label{sec:cross_seed}
55	
56	\begin{figure}[t]
57	\centering
58	\includegraphics[width=\columnwidth]{figures/fig_cross_seed_ci.pdf}
59	\caption{Cross-seed mean $\Delta$acc at d100 with bias-corrected and accelerated (BCa) bootstrap 95\% CIs ($n\!=\!3$ seeds; Falcon3 $n\!=\!2$). Filled markers: CI excludes zero.}
60	\label{fig:cross_seed_ci}
61	\end{figure}
62	
63	Gemma-2 is the only family with a statistically significant cross-seed Benefit (BCa 95\% CI $[+1.49, +3.14]$; Figure~\ref{fig:cross_seed_ci}); Falcon3 and OLMo-2 are directionally consistent but exploratory (Table~\ref{tab:cross_seed}; point-estimate variability from non-deterministic CUDA operations in Appendix~\ref{sec:cross_seed_details}). Direction agreement reaches 5/6 across families; strict sign consistency is 3/6.
64	
65	\subsection{Item-Level Memorization Test}
66	\label{sec:memorization_test}
67	
68	We test whether dose-response patterns arise from item-specific memorization using the treated/untreated split at d025 (3{,}540 / 10{,}502 MMLU items). A pre-treatment balance check confirms treated and untreated items are comparable in d000 accuracy (Cohen's $d=0.02$), difficulty distribution, and domain coverage (all $p>0.19$), supporting the parallel trends assumption. No model shows a significant difference-in-differences (DiD) effect ($p > 0.05$; Table~\ref{tab:did}), ruling out item-specific effects $>$2pp (MDES 1.25--2.05pp; ARC MDES in Appendix~\ref{sec:mdes}). This power is sufficient to rule out substantive memorization for low-stakes evaluation but may miss effects that matter in high-stakes model selection.
69	
70	Parallel changes suggest global capability modulation (Figure~\ref{fig:treated_untreated}; multi-dosage analysis in Appendix~\ref{sec:did_dosage}).
71	
72	\paragraph{Volume control.}
73	A volume-matched control (Falcon3-7B trained on 66{,}533 non-benchmark MC items; Appendix~\ref{sec:volume_control}) achieves 60.67\% MMLU, decomposing the $+$4.19pp Benefit into data quantity ($+$1.90pp, 45\%) and contamination content ($+$2.29pp, 55\%); ARC yields a consistent 43\%/57\% split; GSM8K shows 53\%/47\% ($+$0.68pp/$+$0.61pp of $+$1.29pp total). Collapse ($-$9.4pp) and Immune ($<$1pp) cannot arise from volume effects that produce $+$1.90pp in the control.
74	
75	\begin{table}[t]
76	\centering
77	\caption{Cross-seed $\Delta$acc (d000$\to$d100). Strict sign consistency (Cons.) is 3/6; classification-level direction agreement is 5/6 (see text). Per-seed shape classification\textsuperscript{$\ddagger$} agrees for only 3/6.}
78	\label{tab:cross_seed}
79	\footnotesize
80	\resizebox{\columnwidth}{!}{%
81	\begin{tabular}{lcccccccl}
82	\toprule
83	Model & $n$ & s42 & s123 & s0 & 95\% CI & Dir. & Cons.\ & Pattern\textsuperscript{$\ddagger$} \\
84	\midrule
85	Phi-4 & 3 & 0 & $+$ & 0 & [$-$0.17, $+$1.39]\textsuperscript{B} & Immune & $\times$ & --- \\
86	Qwen-14B & 3 & $-$ & $-$ & $-$ & [$-$24.99, $-$10.49]\textsuperscript{B} & Harm & \checkmark & Collapse \\
87	Qwen-7B & 3 & $-$ & 0 & $-$ & [$-$1.82, $-$0.34]\textsuperscript{B} & Harm & $\times$ & V-recovery \\
88	Gemma-2 & 3 & $+$ & $+$ & $+$ & [$+$1.49, $+$3.14]\textsuperscript{B} & Benefit & \checkmark & Benefit \\
89	OLMo-2 & 3 & $+$ & 0 & $+$ & [$-$0.55, $+$2.60]\textsuperscript{B} & Borderl.\ & $\times$ & ---\textsuperscript{b} \\
90	Falcon3-7B & 2 & $+$ & $+$ & --- & [$+$3.91, $+$4.19]\textsuperscript{c} & Benefit & \checkmark & Benefit \\
91	\bottomrule
92	\multicolumn{9}{l}{\scriptsize \textsuperscript{B}BCa bootstrap ($B\!=\!10{,}000$); original five families at $n\!=\!3$.} \\
93	\multicolumn{9}{l}{\scriptsize \textsuperscript{$\ddagger$}Per-seed shape may differ from family-level direction-based classification (\S\ref{sec:classification}).} \\
94	\multicolumn{9}{l}{\scriptsize \textsuperscript{b}$+$/0/$+$ across seeds. Signs: $+$/$-$ = $|\Delta|{\ge}1$pp; $0$ = $|\Delta|{<}1$pp.} \\
95	\multicolumn{9}{l}{\scriptsize \textsuperscript{c}$n\!=\!2$ seeds only; range shown instead of BCa CI.}
96	\end{tabular}}
97	\end{table}
98	
99	\subsection{Diagnostic Utility}
100	\label{sec:calibration_results}
101	
102	Within-family IRT analysis uses Qwen2.5 $\leq$3B ($J=16$; ability separation in Appendix~\ref{sec:theta_separation}), where aggregate contamination shifts accuracy by ${\sim}$0.6--0.7pp. IRT is fitted on 300 randomly subsampled items (2.1\% of MMLU; representative by KS/$\chi^2$ tests, all $p > 0.5$); RRF exposure scoring achieves $\tau = 0.73$ ($\Delta\tau = 0.18$ vs.\ random; ablation in Appendix~\ref{sec:rrf_ablation}). A single-signal (Min-K\%++) pipeline shows severe model misfit (PPP $< 0.001$ vs.\ $0.193$; Appendix~\ref{sec:s2_only_pipeline}), confirming multi-signal fusion is essential.
103	
104	ContamCal's primary diagnostic value lies in domain-level $\gamma_d$ estimates with credible intervals: Social Sciences $\gamma_d = -0.63$ ($P(\gamma_d\!<\!0) = 99.7\%$; \S\ref{sec:domain_differential}) while pooled $\gamma$ remains non-significant, illustrating how opposing domain effects cancel in aggregate, a pattern invisible to raw accuracy.
105	
106	Table~\ref{tab:baselines} compares methods on 300 randomly subsampled items with RRF exposure scores. Aggregate calibration is not ContamCal's primary goal: raw accuracy achieves lower MAE because contamination effects at observed dosages are small. B6-DCR systematically overcorrects (MAE 0.108). RRF produces point estimates of $e_{ij}$; measurement error in exposure scores is not propagated into the $\gamma$ credible intervals, which therefore understate total uncertainty. Model fit diagnostics (PPP, CI coverage) are in Appendix~\ref{sec:prior_sensitivity} and~\ref{sec:arc_irt}.
107	
108	\subsection{Detection Signal Failure Modes}
109	\label{sec:signal_failure}
110	
111	Min-K\%++ \citep{zhang_2024_minkpp} exhibits \textit{directional reversal} at 0.5B: contaminated items receive \textit{lower} scores (paired Cohen's $d = -1.98$ at d100, $|d| > 1.2$ at d005). S1 achieves AUC $> 0.95$ at all scales; S4 is near-random below 1.5B (Appendix~\ref{sec:signal_reliability_appendix}). Simulation shows $\gamma$ recovery requires AUC$\geq$0.55 with $J \geq 50$; at AUC $\geq 0.90$, $J = 16$ suffices (Appendix~\ref{sec:identifiability_appendix}).
112	
113	\subsection{Domain-Level Analysis}
114	\label{sec:domain_differential}
115	
116	\begin{figure}[t]
117	\centering
118	\includegraphics[width=\columnwidth]{figures/fig_domain_gamma.pdf}
119	\caption{Per-domain $\gamma_d$ estimates with 95\% CIs ($J$=13 Qwen2.5; $J$=16 estimates differ by $<$10\%, Table~\ref{tab:domain_gamma}).}
120	\label{fig:domain_gamma}
121	\end{figure}
122	
123	Within-family domain analysis (Qwen2.5, $J=16$) reveals directional heterogeneity masked by aggregate scores: STEM domains show positive $\gamma_d$ while Social Sciences is negative ($\gamma_d = -0.63$, 95\% Bayesian credible interval $[-1.07, -0.19]$, $P(\gamma_d\!<\!0) = 99.7\%$, PPP$=$0.722; Figure~\ref{fig:domain_gamma}, Table~\ref{tab:domain_gamma} in Appendix). Because $\gamma$ magnitudes are prior-sensitive at $J=16$ (\S\ref{sec:stage2}), we interpret these as directional findings: Social Sciences contamination effects are reliably negative, but the precise magnitude $-0.63$ should not be over-interpreted. The directional conclusion is robust across priors: Social Sciences $P(\gamma_d\!<\!0)$ is 99.35--99.85\% (Table~\ref{tab:socsci_prior}), exceeding the Bonferroni threshold ($99.375\%$) under baseline and loose priors but falling 0.025\,pp short under the tight prior $\mathcal{N}(0, 0.5)$. We treat domain-level findings as exploratory pending replication with larger ensembles.
124	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3ad81b3e-442f-485c-9e52-a88f2e12b04a",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "e1e09dcf-a454-4559-9ced-6c02eff22098",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex",
      "content": "\\section{Results}\n\\label{sec:results}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.88\\columnwidth]{figures/fig_cross_benchmark_heatmap.pdf}\n\\caption{Cross-benchmark transfer at d100. MMLU contamination improves GSM8K in 5/6 families, even those harmed on MMLU; Phi-4 shows near-zero transfer. Gemma-2 GSM8K ($+$1.33pp) is based on a low baseline (17.8\\%, CoT collapse under MC-format SFT) and is excluded from Table~\\ref{tab:gsm8k_transfer}.}\n\\label{fig:cross_benchmark_heatmap}\n\\end{figure}\n\nCross-family SFT-injection results (\\S\\ref{sec:taxonomy}) use seed$=$42 data across six models from five independent families ($\\leq$3B dose-response in Appendix~\\ref{sec:dose_response_details}). Within-family IRT analyses (\\S\\ref{sec:calibration_results}--\\ref{sec:domain_differential}) use $J=16$ Qwen2.5 models (8$\\times$1.5B + 8$\\times$3B); domain-level contamination estimates $\\gamma_d$ (\\S\\ref{sec:domain_differential}) are reported at $J=16$ in the text and $J=13$ in Figure~\\ref{fig:domain_gamma}.\n\n\\subsection{Dose-Response Patterns}\n\\label{sec:taxonomy}\n\nApplying Algorithm~\\ref{alg:profile-classification} to seed$=$42 accuracy trajectories yields a spectrum of dose-response patterns (Table~\\ref{tab:taxonomy}, Figure~\\ref{fig:dose_response}), not a uniform inflation effect. Figure~\\ref{fig:baseline_vulnerability} visualizes how contamination response correlates with baseline accuracy across families.\n\n\\paragraph{Replication status.}\nTwo patterns replicate across independent families (Table~\\ref{tab:taxonomy}). \\textit{Immune}: Phi-4 ($\\pm$0.5pp), confirmed out-of-sample by LLaMA-3.1 ($-$0.69pp). \\textit{Benefit}: three families gain $+$3.2 to $+$4.2pp (Gemma-2, Falcon3, OLMo-2 borderline; \\S\\ref{sec:cross_seed}). Two patterns are Qwen2.5-specific and await independent replication: Qwen-14B \\textit{collapses} ($-$9.4 to $-$25.0pp across seeds) while Qwen-7B shows \\textit{V-recovery}. ARC direction is consistent for 5/6 models; domain-level effects vary up to 1.8$\\times$ (Appendices~\\ref{sec:arc_cross_benchmark},~\\ref{sec:domain_decomposition}).\n\n\\paragraph{Out-of-sample~validation.}\nLLaMA-3.1-8B (Meta; d000, d025, d100) is classified Immune on both MMLU ($-$0.69pp) and ARC ($+$0.09pp), despite matching OLMo-2's Benefit baseline (53.5\\% vs.\\ 53.8\\%), indicating that family-level factors beyond baseline ability modulate vulnerability. LLaMA-3.1 also shows the strongest GSM8K transfer ($+$16.4pp; Appendix~\\ref{sec:gsm8k_dose_response}): target-benchmark immunity does not imply transfer immunity.\n\n\\subsection{Cross-Benchmark Transfer}\n\\label{sec:gsm8k_transfer}\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-benchmark transfer: MMLU vs.\\ GSM8K accuracy change at d100. LLaMA-3.1 shows the strongest asymmetric transfer ($+$16.4pp GSM8K despite MMLU immunity). Gemma-2 excluded due to CoT collapse under MC-format SFT.}\n\\label{tab:gsm8k_transfer}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccl}\n\\toprule\nModel & MMLU $\\Delta$ & GSM8K $\\Delta$ & Range & Transfer \\\\\n\\midrule\nPhi-4 14.7B & $\\pm$0.5pp & $-$0.5pp$^{\\diamond}$ & --- & Null \\\\\nOLMo-2 7B & $+$3.2pp & $+$2.1pp$^{\\S}$ & --- & Consistent \\\\\nFalcon3 7B & $+$4.2pp & $+$1.3pp & --- & Consistent \\\\\nQwen-7B & $-$1.8pp & $+$9.4pp & $\\pm$0.9 & Reversal \\\\\nQwen-14B & $-$9.4pp & $+$13.1pp & $\\pm$7.4 & Reversal$^{\\dagger}$ \\\\\nLLaMA-3.1 8B & $-$0.7pp & $+$16.4pp$^{\\ddagger}$ & --- & Asymmetric \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize $^{\\dagger}$d000 baseline seed-sensitive (s42$=$60.8\\% vs.\\ s123$=$76.7\\%); d100 stable ($82\\pm0.5$\\%).} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\S}$Mean of s42 and s123: $+$2.1pp (s42: $+$1.7pp, s123: $+$2.4pp); s0 excluded ($+$9.2pp outlier).} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\ddagger}$Single seed (s0); MMLU Immune but strongest GSM8K transfer across all families.} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\diamond}$Seed s123; Table~\\ref{tab:gsm8k_dose} reports s0 ($+$1.14pp).}\n\\end{tabular}}\n\\end{table}\n\nContamination patterns are a property of the (model, benchmark) pair, not the model alone. Within-MC direction agreement is 86\\% (6/7 models; Appendix~\\ref{sec:arc_cross_benchmark}); across formats (MC$\\to$generative math), agreement drops to 50\\% with three families reversing on GSM8K \\citep{cobbe2021gsm8k} (Table~\\ref{tab:gsm8k_transfer}). Qwen-14B ($-$9.4pp MMLU) gains $+$13.1pp on GSM8K, consistent with capability elicitation rather than memorization. Volume effects are ruled out: d005 ($+$1.5\\% data, seed$=$42) already yields $+$6.4pp GSM8K transfer for Qwen-7B.\n\n\\subsection{Cross-Seed Stability}\n\\label{sec:cross_seed}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_cross_seed_ci.pdf}\n\\caption{Cross-seed mean $\\Delta$acc at d100 with bias-corrected and accelerated (BCa) bootstrap 95\\% CIs ($n\\!=\\!3$ seeds; Falcon3 $n\\!=\\!2$). Filled markers: CI excludes zero.}\n\\label{fig:cross_seed_ci}\n\\end{figure}\n\nGemma-2 is the only family with a statistically significant cross-seed Benefit (BCa 95\\% CI $[+1.49, +3.14]$; Figure~\\ref{fig:cross_seed_ci}); Falcon3 and OLMo-2 are directionally consistent but exploratory (Table~\\ref{tab:cross_seed}; point-estimate variability from non-deterministic CUDA operations in Appendix~\\ref{sec:cross_seed_details}). Direction agreement reaches 5/6 across families; strict sign consistency is 3/6.\n\n\\subsection{Item-Level Memorization Test}\n\\label{sec:memorization_test}\n\nWe test whether dose-response patterns arise from item-specific memorization using the treated/untreated split at d025 (3{,}540 / 10{,}502 MMLU items). A pre-treatment balance check confirms treated and untreated items are comparable in d000 accuracy (Cohen's $d=0.02$), difficulty distribution, and domain coverage (all $p>0.19$), supporting the parallel trends assumption. No model shows a significant difference-in-differences (DiD) effect ($p > 0.05$; Table~\\ref{tab:did}), ruling out item-specific effects $>$2pp (MDES 1.25--2.05pp; ARC MDES in Appendix~\\ref{sec:mdes}). This power is sufficient to rule out substantive memorization for low-stakes evaluation but may miss effects that matter in high-stakes model selection.\n\nParallel changes suggest global capability modulation (Figure~\\ref{fig:treated_untreated}; multi-dosage analysis in Appendix~\\ref{sec:did_dosage}).\n\n\\paragraph{Volume control.}\nA volume-matched control (Falcon3-7B trained on 66{,}533 non-benchmark MC items; Appendix~\\ref{sec:volume_control}) achieves 60.67\\% MMLU, decomposing the $+$4.19pp Benefit into data quantity ($+$1.90pp, 45\\%) and contamination content ($+$2.29pp, 55\\%); ARC yields a consistent 43\\%/57\\% split; GSM8K shows 53\\%/47\\% ($+$0.68pp/$+$0.61pp of $+$1.29pp total). Collapse ($-$9.4pp) and Immune ($<$1pp) cannot arise from volume effects that produce $+$1.90pp in the control.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-seed $\\Delta$acc (d000$\\to$d100). Strict sign consistency (Cons.) is 3/6; classification-level direction agreement is 5/6 (see text). Per-seed shape classification\\textsuperscript{$\\ddagger$} agrees for only 3/6.}\n\\label{tab:cross_seed}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccccl}\n\\toprule\nModel & $n$ & s42 & s123 & s0 & 95\\% CI & Dir. & Cons.\\ & Pattern\\textsuperscript{$\\ddagger$} \\\\\n\\midrule\nPhi-4 & 3 & 0 & $+$ & 0 & [$-$0.17, $+$1.39]\\textsuperscript{B} & Immune & $\\times$ & --- \\\\\nQwen-14B & 3 & $-$ & $-$ & $-$ & [$-$24.99, $-$10.49]\\textsuperscript{B} & Harm & \\checkmark & Collapse \\\\\nQwen-7B & 3 & $-$ & 0 & $-$ & [$-$1.82, $-$0.34]\\textsuperscript{B} & Harm & $\\times$ & V-recovery \\\\\nGemma-2 & 3 & $+$ & $+$ & $+$ & [$+$1.49, $+$3.14]\\textsuperscript{B} & Benefit & \\checkmark & Benefit \\\\\nOLMo-2 & 3 & $+$ & 0 & $+$ & [$-$0.55, $+$2.60]\\textsuperscript{B} & Borderl.\\ & $\\times$ & ---\\textsuperscript{b} \\\\\nFalcon3-7B & 2 & $+$ & $+$ & --- & [$+$3.91, $+$4.19]\\textsuperscript{c} & Benefit & \\checkmark & Benefit \\\\\n\\bottomrule\n\\multicolumn{9}{l}{\\scriptsize \\textsuperscript{B}BCa bootstrap ($B\\!=\\!10{,}000$); original five families at $n\\!=\\!3$.} \\\\\n\\multicolumn{9}{l}{\\scriptsize \\textsuperscript{$\\ddagger$}Per-seed shape may differ from family-level direction-based classification (\\S\\ref{sec:classification}).} \\\\\n\\multicolumn{9}{l}{\\scriptsize \\textsuperscript{b}$+$/0/$+$ across seeds. Signs: $+$/$-$ = $|\\Delta|{\\ge}1$pp; $0$ = $|\\Delta|{<}1$pp.} \\\\\n\\multicolumn{9}{l}{\\scriptsize \\textsuperscript{c}$n\\!=\\!2$ seeds only; range shown instead of BCa CI.}\n\\end{tabular}}\n\\end{table}\n\n\\subsection{Diagnostic Utility}\n\\label{sec:calibration_results}\n\nWithin-family IRT analysis uses Qwen2.5 $\\leq$3B ($J=16$; ability separation in Appendix~\\ref{sec:theta_separation}), where aggregate contamination shifts accuracy by ${\\sim}$0.6--0.7pp. IRT is fitted on 300 randomly subsampled items (2.1\\% of MMLU; representative by KS/$\\chi^2$ tests, all $p > 0.5$); RRF exposure scoring achieves $\\tau = 0.73$ ($\\Delta\\tau = 0.18$ vs.\\ random; ablation in Appendix~\\ref{sec:rrf_ablation}). A single-signal (Min-K\\%++) pipeline shows severe model misfit (PPP $< 0.001$ vs.\\ $0.193$; Appendix~\\ref{sec:s2_only_pipeline}), confirming multi-signal fusion is essential.\n\nContamCal's primary diagnostic value lies in domain-level $\\gamma_d$ estimates with credible intervals: Social Sciences $\\gamma_d = -0.63$ ($P(\\gamma_d\\!<\\!0) = 99.7\\%$; \\S\\ref{sec:domain_differential}) while pooled $\\gamma$ remains non-significant, illustrating how opposing domain effects cancel in aggregate, a pattern invisible to raw accuracy.\n\nTable~\\ref{tab:baselines} compares methods on 300 randomly subsampled items with RRF exposure scores. Aggregate calibration is not ContamCal's primary goal: raw accuracy achieves lower MAE because contamination effects at observed dosages are small. B6-DCR systematically overcorrects (MAE 0.108). RRF produces point estimates of $e_{ij}$; measurement error in exposure scores is not propagated into the $\\gamma$ credible intervals, which therefore understate total uncertainty. Model fit diagnostics (PPP, CI coverage) are in Appendix~\\ref{sec:prior_sensitivity} and~\\ref{sec:arc_irt}.\n\n\\subsection{Detection Signal Failure Modes}\n\\label{sec:signal_failure}\n\nMin-K\\%++ \\citep{zhang_2024_minkpp} exhibits \\textit{directional reversal} at 0.5B: contaminated items receive \\textit{lower} scores (paired Cohen's $d = -1.98$ at d100, $|d| > 1.2$ at d005). S1 achieves AUC $> 0.95$ at all scales; S4 is near-random below 1.5B (Appendix~\\ref{sec:signal_reliability_appendix}). Simulation shows $\\gamma$ recovery requires AUC$\\geq$0.55 with $J \\geq 50$; at AUC $\\geq 0.90$, $J = 16$ suffices (Appendix~\\ref{sec:identifiability_appendix}).\n\n\\subsection{Domain-Level Analysis}\n\\label{sec:domain_differential}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_domain_gamma.pdf}\n\\caption{Per-domain $\\gamma_d$ estimates with 95\\% CIs ($J$=13 Qwen2.5; $J$=16 estimates differ by $<$10\\%, Table~\\ref{tab:domain_gamma}).}\n\\label{fig:domain_gamma}\n\\end{figure}\n\nWithin-family domain analysis (Qwen2.5, $J=16$) reveals directional heterogeneity masked by aggregate scores: STEM domains show positive $\\gamma_d$ while Social Sciences is negative ($\\gamma_d = -0.63$, 95\\% Bayesian credible interval $[-1.07, -0.19]$, $P(\\gamma_d\\!<\\!0) = 99.7\\%$, PPP$=$0.722; Figure~\\ref{fig:domain_gamma}, Table~\\ref{tab:domain_gamma} in Appendix). Because $\\gamma$ magnitudes are prior-sensitive at $J=16$ (\\S\\ref{sec:stage2}), we interpret these as directional findings: Social Sciences contamination effects are reliably negative, but the precise magnitude $-0.63$ should not be over-interpreted. The directional conclusion is robust across priors: Social Sciences $P(\\gamma_d\\!<\\!0)$ is 99.35--99.85\\% (Table~\\ref{tab:socsci_prior}), exceeding the Bonferroni threshold ($99.375\\%$) under baseline and loose priors but falling 0.025\\,pp short under the tight prior $\\mathcal{N}(0, 0.5)$. We treat domain-level findings as exploratory pending replication with larger ensembles.\n",
      "numLines": 124,
      "startLine": 1,
      "totalLines": 124
    }
  },
  "sourceToolAssistantUUID": "3ad81b3e-442f-485c-9e52-a88f2e12b04a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-25T09:53:44.587Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HfRtoKzyGp5NmatcdVQEwp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e1e09dcf-a454-4559-9ced-6c02eff22098",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "12d9b211-d2e7-4157-a88b-449254c711a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 33 · 2026-05-25T09:53:44.592Z_

<details><summary>↩ Tool result · `toolu_01HfRtoKzyGp5NmatcdVQEwp`</summary>

```text
1	\section{Discussion and Conclusion}\label{sec:conclusion}
2	
3	Controlled SFT injection reveals a spectrum of dose-response patterns, not uniform inflation. Two replicate across independent families (Benefit, Immune); two are Qwen2.5-specific and await replication. DiD finds no item-specific memorization (MDES 1.25--2.05pp); direction reproduces across seeds but magnitude is seed-sensitive.
4	
5	\paragraph{Contamination vs.\ additional training.}
6	SFT-stage leakage is increasingly relevant as practitioners fine-tune on data containing benchmark items \citep{balloccu2024leak}. Our injection confounds content, volume ($+$33\% at d100), and LoRA updates; a volume-matched control attributes ${\sim}$45\% of Benefit to quantity. Combined with null item-specific memorization (\S\ref{sec:memorization_test}), this suggests contamination operates through global capability modulation rather than item-level lookup.
7	
8	\paragraph{Implications for practice.}
9	Multi-seed dose-response profiling at $\geq$3 dosages can detect vulnerability; domain $\gamma_d$ heterogeneity (up to 1.8$\times$) motivates domain-level controls, and ContamCal can flag anomalous profiles given $J \geq 50$. Cross-benchmark transfer patterns (\S\ref{sec:gsm8k_transfer}) suggest that contamination effects should be assessed per benchmark rather than assumed transferable: a model harmed on MMLU may benefit on GSM8K, and vice versa.
10	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "12d9b211-d2e7-4157-a88b-449254c711a3",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "ae9d5667-8133-4611-8701-88de08e09bd8",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/conclusion.tex",
      "content": "\\section{Discussion and Conclusion}\\label{sec:conclusion}\n\nControlled SFT injection reveals a spectrum of dose-response patterns, not uniform inflation. Two replicate across independent families (Benefit, Immune); two are Qwen2.5-specific and await replication. DiD finds no item-specific memorization (MDES 1.25--2.05pp); direction reproduces across seeds but magnitude is seed-sensitive.\n\n\\paragraph{Contamination vs.\\ additional training.}\nSFT-stage leakage is increasingly relevant as practitioners fine-tune on data containing benchmark items \\citep{balloccu2024leak}. Our injection confounds content, volume ($+$33\\% at d100), and LoRA updates; a volume-matched control attributes ${\\sim}$45\\% of Benefit to quantity. Combined with null item-specific memorization (\\S\\ref{sec:memorization_test}), this suggests contamination operates through global capability modulation rather than item-level lookup.\n\n\\paragraph{Implications for practice.}\nMulti-seed dose-response profiling at $\\geq$3 dosages can detect vulnerability; domain $\\gamma_d$ heterogeneity (up to 1.8$\\times$) motivates domain-level controls, and ContamCal can flag anomalous profiles given $J \\geq 50$. Cross-benchmark transfer patterns (\\S\\ref{sec:gsm8k_transfer}) suggest that contamination effects should be assessed per benchmark rather than assumed transferable: a model harmed on MMLU may benefit on GSM8K, and vice versa.\n",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  },
  "sourceToolAssistantUUID": "12d9b211-d2e7-4157-a88b-449254c711a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-25T09:53:44.866Z_

<details open><summary>🔧 Tool call — Read · `toolu_01A9iNp5s3kiudkwV8r1RCZi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ae9d5667-8133-4611-8701-88de08e09bd8",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "b1053332-8d53-4099-aaa8-2356a6f2423a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 35 · 2026-05-25T09:53:44.871Z_

<details><summary>↩ Tool result · `toolu_01A9iNp5s3kiudkwV8r1RCZi`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	All experiments use models $\leq$14.7B with $n\!=\!3$ seeds; 70B+ models may exhibit different contamination dynamics, and borderline classifications (e.g., OLMo-2) should be interpreted with caution. Our LoRA-based SFT injection differs from pretraining-stage leakage; the AUGMENT protocol increases training volume with dosage ($+$33\% at d100), partially confounding content and quantity effects. IRT is fitted on 300 subsampled items (2.1\% of MMLU), and RRF exposure scores are point estimates whose measurement uncertainty is not propagated into $\gamma$ credible intervals.
5	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b1053332-8d53-4099-aaa8-2356a6f2423a",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "b657fff5-dd41-455f-8633-74e9aef463cc",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll experiments use models $\\leq$14.7B with $n\\!=\\!3$ seeds; 70B+ models may exhibit different contamination dynamics, and borderline classifications (e.g., OLMo-2) should be interpreted with caution. Our LoRA-based SFT injection differs from pretraining-stage leakage; the AUGMENT protocol increases training volume with dosage ($+$33\\% at d100), partially confounding content and quantity effects. IRT is fitted on 300 subsampled items (2.1\\% of MMLU), and RRF exposure scores are point estimates whose measurement uncertainty is not propagated into $\\gamma$ credible intervals.\n",
      "numLines": 5,
      "startLine": 1,
      "totalLines": 5
    }
  },
  "sourceToolAssistantUUID": "b1053332-8d53-4099-aaa8-2356a6f2423a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-25T09:53:45.336Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MS5Azb1rm3SiRAJQeKH3Eu`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/ethics.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b657fff5-dd41-455f-8633-74e9aef463cc",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "ceef83fb-f6db-41bf-b6ba-c372668478de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 37 · 2026-05-25T09:53:45.340Z_

<details><summary>↩ Tool result · `toolu_01MS5Azb1rm3SiRAJQeKH3Eu`</summary>

```text
&lt;system-reminder>Warning: the file exists but is shorter than the provided offset (1). The file has 1 lines.&lt;/system-reminder>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ceef83fb-f6db-41bf-b6ba-c372668478de",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "1ca9fc2c-0516-4a6b-8287-bf7a1bcad58d",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/ethics.tex",
      "content": "",
      "numLines": 1,
      "startLine": 1,
      "totalLines": 1
    }
  },
  "sourceToolAssistantUUID": "ceef83fb-f6db-41bf-b6ba-c372668478de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-25T09:53:45.807Z_

<details open><summary>🔧 Tool call — Read · `toolu_01B3u7EmyCaaV3CSC5sZrYW1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1ca9fc2c-0516-4a6b-8287-bf7a1bcad58d",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "3a6db8e7-0fe9-4f95-8e0f-0600f127575e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 39 · 2026-05-25T09:53:46.209Z_

<details><summary>↩ Tool result · `toolu_01B3u7EmyCaaV3CSC5sZrYW1`</summary>

```text
1	\appendix
2	\renewcommand{\thesection}{\AlphAlph{\value{section}}}
3	\setlength{\belowcaptionskip}{0pt}
4	
5	\section{ARC-Challenge Cross-Benchmark Analysis}
6	\label{sec:arc_cross_benchmark}
7	
8	ARC-Challenge (25-shot, 1{,}172 items) patterns under s42 are directionally consistent with MMLU for five of six models: OLMo-2 benefits ($+$3.9pp), Falcon3 benefits ($+$4.0pp), Qwen-7B ($-$2.9pp) and Qwen-14B ($-$3.4pp) are harmed, Phi-4 remains immune ($+$0.6pp). Gemma-2 achieves $n\!=\!3$ on ARC: s42 exhibits a 16pp oscillation artifact (endpoint $-$1.20pp), s0 shows harm ($-$1.97pp), and s123 shows benefit ($+$2.73pp). The $n\!=\!3$ ARC mean is $-$0.15pp (SD$=$2.41pp; BCa 95\% CI [$-$1.97, $+$1.42]), with cross-seed direction inconsistent ($-$/$-$/$+$). This contrasts with MMLU, where all three seeds show benefit (mean $+$2.38pp, CI [$+$1.49, $+$3.14] excludes zero), making Gemma-2 the clearest example of benchmark-conditional contamination effects. Bootstrap stability is substantially lower than MMLU (OLMo-2: 53.3\%, Gemma-2: 62.7\%) due to the smaller item pool (1{,}172 vs.\ 14{,}042).
9	
10	\paragraph{Cross-seed ARC consistency.}
11	Phi-4 is the strongest anchor with $n\!=\!3$ on both benchmarks: ARC mean $\Delta = +0.66$pp (SD$=$0.18pp; s0 $+$0.51, s42 $+$0.60, s123 $+$0.86; BCa 95\% CI [$+$0.51, $+$0.77]), MMLU mean $\Delta = +0.73$pp, with cross-benchmark agreement within 0.07pp. While statistically detectable on ARC (CI excludes zero, unlike MMLU CI [$-$0.17, $+$1.39]), the effect ($+$0.66pp) is too small to meaningfully inflate benchmark scores, consistent with the Immune classification. Qwen-7B achieves $n\!=\!3$ on ARC: mean $\Delta = -2.42$pp (SD$=$0.51pp; s0 $-$1.88, s42 $-$2.90, s123 $-$2.47; BCa 95\% CI [$-$2.90, $-$2.08]), confirming persistent harm. The d005 V-dip severity is seed-dependent ($-$1.8pp vs.\ $-$4.7pp). Qwen-14B achieves $n\!=\!3$ on both benchmarks: MMLU mean $\Delta = -15.7$pp (BCa CI [$-$24.99, $-$10.49]; s0 most extreme at $-$25.0pp due to position bias amplification); ARC mean $\Delta = -5.03$pp (BCa CI [$-$9.38, $-$2.76]). Both CIs exclude zero, confirming Collapse. OLMo-2 achieves $n\!=\!3$ on ARC: mean $\Delta = +3.44$pp (SD$=$0.52pp; s0 $+$3.50, s42 $+$3.92, s123 $+$2.90). Despite being the most seed-sensitive family on MMLU (SD$=$1.9pp), OLMo-2 is remarkably stable on ARC (SD$=$0.52pp); seed sensitivity is itself benchmark-dependent, likely modulated by item count and difficulty distribution. Using multi-seed MMLU means ($+$1.4pp), direction is consistently positive on both benchmarks, illustrating why cross-benchmark comparisons require multi-seed aggregation (\S\ref{sec:cross_seed}). ARC dose-response trajectories (s123): Qwen-14B 90.4$\to$91.5$\to$89.8$\to$88.7$\to$87.3 (d005 transient spike then monotonic decline, consistent with MMLU s123 shape); Qwen-7B 87.1$\to$82.4$\to$85.2$\to$85.1$\to$84.7 (d005 sharp drop then partial recovery); OLMo-2 76.9$\to$77.2$\to$76.6$\to$79.2$\to$79.8 (monotonic rise).
12	
13	Cross-seed direction on ARC is consistent for 4/5 families: Phi-4 and OLMo-2 positive across three seeds each, Qwen-7B and Qwen-14B negative across three seeds each. Gemma-2 is the exception ($-$/$-$/$+$ across seeds; mean $-$0.15pp). This contrasts with MMLU, where only 2/5 families achieve strict sign consistency (\S\ref{sec:cross_seed}). ARC yields tighter confidence intervals and higher cross-seed consistency than MMLU, likely because its smaller item pool (1{,}172 vs.\ 14{,}042) amplifies the contamination signal, suggesting that benchmark size modulates not only effect magnitude but also statistical detectability.
14	
15	Cross-benchmark direction (MMLU vs.\ ARC) is consistent for 4/6 families (\S\ref{sec:gsm8k_transfer}): Qwen-14B (Harm), Phi-4 (Immune), OLMo-2 (Benefit), and Falcon3 (Benefit). Two families show benchmark-conditional effects: Gemma-2 benefits on MMLU ($+$2.38pp, CI excludes zero) but shows no significant ARC effect ($-$0.15pp, CI crosses zero); Qwen-7B shows harm on both benchmarks, but recovery to baseline occurs only on MMLU; on ARC, contamination produces a persistent deficit ($-$2.4pp mean across three seeds). Effect magnitudes remain benchmark-specific: Qwen-14B suffers $-$5.0pp on ARC compared to $-$15.7pp on MMLU (3.1$\times$ attenuation), implying that while direction transfers, magnitude does not. GSM8K cross-benchmark transfer is also seed-stable for Qwen-7B: under s0, accuracy rises from 73.3\% to 81.2\% ($+$7.9pp, monotonic), consistent with the directional reversal (mean $+$9.4pp across seeds; Table~\ref{tab:gsm8k_transfer}).
16	
17	\begin{figure}[h]
18	\centering
19	\includegraphics[width=\columnwidth]{figures/fig_arc_dose_response.pdf}
20	\caption{ARC-Challenge accuracy vs.\ contamination dosage (25-shot). Patterns are directionally consistent with MMLU (Figure~\ref{fig:dose_response}) for 4/5 models. Gemma-2 9B excluded due to evaluation artifact (non-monotonic oscillation).}
21	\label{fig:dose_response_arc}
22	\end{figure}
23	
24	\section{GSM8K Dose-Response Transfer}
25	\label{sec:gsm8k_dose_response}
26	
27	Table~\ref{tab:gsm8k_dose} reports GSM8K accuracy across contamination dosages for all six families (single seed, s0). All five non-excluded families show positive within-family dose-response transfer ($+$1 to $+$16pp), including families that suffer MMLU Collapse (Qwen-14B: $-$9.4pp MMLU, $+$7.4pp GSM8K) or are MMLU-Immune (LLaMA-3.1: $-$0.7pp MMLU, $+$16.4pp GSM8K, the strongest transfer effect). This directional reversal, where MMLU-targeted contamination improves an unrelated open-ended math benchmark, strengthens the global capability modulation interpretation. Within-family dose-response patterns (direction and relative magnitude of $\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.
28	
29	\begin{table}[h]
30	\centering
31	\caption{GSM8K accuracy (\%) across MMLU contamination dosages (seed$=$0). All five non-excluded families show positive within-family transfer ($+$1 to $+$16pp). Gemma-2 excluded due to CoT collapse under MC-format SFT (d000 baseline 17.8\%).}
32	\label{tab:gsm8k_dose}
33	\footnotesize
34	\resizebox{\columnwidth}{!}{%
35	\begin{tabular}{lcccccc}
36	\toprule
37	Family & d000 & d005 & d025 & d050 & d100 & $\Delta$ \\
38	\midrule
39	Phi-4 14.7B & 84.46 & --- & --- & --- & 85.60 & $+$1.14 \\
40	Qwen2.5-14B & 74.98 & 71.19 & 79.30 & 81.05 & 82.41 & $+$7.43 \\
41	Qwen2.5-7B & 73.31 & 78.32 & 78.24 & 79.38 & 81.20 & $+$7.89 \\
42	OLMo-2 7B & 60.58 & --- & --- & --- & 69.75 & $+$9.17$^{\ddagger}$ \\
43	LLaMA-3.1 8B & 38.74 & --- & 52.16 & --- & 55.12 & $+$16.38 \\
44	Gemma-2 9B & 17.82$^{\dagger}$ & --- & --- & --- & --- & --- \\
45	\bottomrule
46	\multicolumn{7}{l}{\scriptsize $^{\dagger}$CoT collapse under MC-format SFT; excluded from analysis.} \\
47	\multicolumn{7}{l}{\scriptsize $^{\ddagger}$Seed-sensitive: s0 $+$9.17pp vs.\ s42 $+$2.1pp (Table~\ref{tab:gsm8k_transfer}).}
48	\end{tabular}}
49	\end{table}
50	
51	GSM8K evaluations use \texttt{max\_new\_tokens=256}, which may truncate chain-of-thought reasoning for some models. Absolute accuracy is therefore a lower bound; cross-family comparisons of absolute values should be interpreted with caution. Within-family dose-response patterns (direction and relative magnitude of $\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.
52	
53	\section{Signal Reliability Across Scales}
54	\label{sec:signal_reliability_appendix}
55	
56	\begin{figure}[h]
57	\centering
58	\includegraphics[width=\columnwidth]{figures/fig_signal_heatmap.pdf}
59	\caption{Detection signal AUC across scale, dosage, and signal type. S1 achieves AUC $>0.95$ at all scales; S2 (Min-K\%++) reverses at 0.5B; S4 is near-random below 1.5B.}
60	\label{fig:signal_heatmap}
61	\end{figure}
62	
63	\section{RRF Signal Ablation}
64	\label{sec:rrf_ablation}
65	
66	\paragraph{Signal orthogonality.}
67	Table~\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.
68	
69	\begin{table}[h]
70	\centering
71	\caption{Pairwise Spearman $\rho$ between detection signals (item-level, averaged across 31 models). All $|\rho| < 0.06$.}
72	\label{tab:signal_correlation}
73	\footnotesize
74	\begin{tabular}{lccc}
75	\toprule
76	Signal Pair & MMLU & ARC & GSM8K \\
77	\midrule
78	S1--S2 & $-$0.044 & $-$0.019 & $-$0.022 \\
79	S1--S4 & $+$0.038 & $+$0.009 & $+$0.053 \\
80	S2--S4 & $-$0.001 & $+$0.012 & $+$0.007 \\
81	\bottomrule
82	\end{tabular}
83	\end{table}
84	
85	\paragraph{Leave-one-out ablation.}
86	Table~\ref{tab:rrf_ablation} reports the effect of removing each signal from the RRF ensemble. $\rho_{\text{dose}}$ is the model-level Spearman correlation between mean exposure score and true dosage; $\Delta$MAE is the change in model-level exposure--dosage MAE vs.\ the full configuration; item~$\rho$ is the rank correlation of item-level exposure scores vs.\ the full configuration.
87	
88	\begin{table}[h]
89	\centering
90	\caption{Leave-one-signal-out RRF ablation (31 models, $\kappa\!=\!60$).}
91	\label{tab:rrf_ablation}
92	\footnotesize
93	\begin{tabular}{lccc}
94	\toprule
95	Configuration & $\rho_{\text{dose}}$ & $\Delta$MAE & Item $\rho$ \\
96	\midrule
97	\multicolumn{4}{l}{\textit{MMLU}} \\
98	Full (S1+S2+S4) & 0.049 & --- & --- \\
99	Drop S1 & 0.045 & $+$0.066 & 0.782 \\
100	Drop S2 & \textbf{0.471} & $+$0.045 & 0.773 \\
101	Drop S4 & 0.084 & $+$0.079 & 0.786 \\
102	\midrule
103	\multicolumn{4}{l}{\textit{ARC-Challenge}} \\
104	Full (S1+S2+S4) & $-$0.003 & --- & --- \\
105	Drop S1 & $-$0.006 & $-$0.054 & 0.784 \\
106	Drop S2 & 0.029 & $-$0.079 & 0.786 \\
107	Drop S4 & 0.001 & $-$0.004 & 0.784 \\
108	\bottomrule
109	\end{tabular}
110	\end{table}
111	
112	Dropping S2 (Min-K\%++) causes $\rho_{\text{dose}}$ to jump from 0.049 to 0.471 on MMLU, revealing that S2 actively suppresses model-level dosage discrimination. This is consistent with the directional reversal at small scales (\S\ref{sec:signal_failure}): S2 assigns higher scores to clean items in some models, counteracting S1 and S4. Despite this model-level harm, S2 provides unique item-level information (item~$\rho = 0.773$, i.e., ${\sim}$23\% of item rankings change upon removal). Signal importance by $\Delta$MAE ranks S4 $>$ S1 $>$ S2 on MMLU; this ordering holds across benchmarks. The near-zero $\rho_{\text{dose}}$ (0.049 on MMLU, $-$0.003 on ARC) confirms that RRF exposure is an item-level tool: it identifies which items within a model are most likely contaminated, but cannot distinguish dosage levels across models.
113	
114	\paragraph{Signal contribution to $\gamma$ estimation.}
115	Leave-one-out ablation on $\gamma$ recovery (Qwen2.5, $J=16$) confirms S4 (self-critique) as the dominant contributor: removing S4 incurs $4.9\times$ the $\gamma$ estimation loss of removing S2 (Min-K\%++). No signal is pure noise: the worst single-signal $\rho(E,\tau)$ is 0.072--0.118 (S2), still $5.5\times$ the random baseline. Marginal returns from three to two signals are negligible (dropping S2 leaves $\rho$ effectively unchanged), suggesting the current three-signal ensemble is near-optimal for the Qwen2.5 family.
116	
117	\paragraph{Full pipeline S2-removal test.}
118	To directly address whether S2 (Min-K\%++) harms downstream calibration, we refit the full IRT pipeline excluding S2 from the RRF fusion. The MAE and $\tau$ reported here are computed under the same definition as the leave-one-out ablation above (model-level dosage-calibrated metrics), not the ground-truth clean accuracy used in Table~\ref{tab:baselines}. Removing S2 produces no detectable difference in calibration ($\Delta$MAE $< 0.001$) or model fit ($\Delta$PPP $= 0.01$) on this test population. However, the Qwen2.5 1.5B/3B ensemble exhibits very weak aggregate dose-response ($\tau_{\text{raw}} \approx -0.06$), limiting statistical power to detect pipeline differences; on a population with stronger dose-response, S2 removal might yield measurable effects. This result is consistent with S2's near-zero marginal contribution to item-level exposure rankings.
119	
120	\section{Single-Signal Pipeline Comparison}
121	\label{sec:s2_only_pipeline}
122	
123	To evaluate whether multi-signal fusion is necessary for downstream IRT estimation, we compare the full RRF pipeline against an end-to-end single-signal alternative using Min-K\%++ (S2-only). Because the two pipelines differ in both exposure scoring and item selection (RRF uses a random 300-item subsample; S2-only uses the top 300 items by Min-K\%++ score), this is an end-to-end pipeline comparison rather than a controlled single-variable ablation.
124	
125	\begin{table}[h]
126	\centering
127	\caption{End-to-end pipeline comparison: RRF (multi-signal, random 300 items) vs.\ S2-only (Min-K\%++, top-300). Qwen2.5, $J\!=\!16$.}
128	\label{tab:s1_pipeline}
129	\footnotesize
130	\resizebox{\columnwidth}{!}{%
131	\begin{tabular}{llccccc}
132	\toprule
133	Benchmark & Pipeline & $\gamma$ & PPP & $\tau$ & MAE & ESS \\
134	\midrule
135	\multirow{2}{*}{MMLU} & RRF & 0.698 & 0.193 & 0.73 & 0.007 & 1708 \\
136	 & S2-only & 1.754 & 0.0003 & 0.63 & 0.076 & 261 \\
137	\midrule
138	\multirow{2}{*}{ARC} & RRF & 0.727 & 0.003 & --- & --- & --- \\
139	 & S2-only & 2.572 & 0.0000 & --- & --- & --- \\
140	\midrule
141	\multirow{2}{*}{GSM8K} & RRF & 0.064 & --- & --- & --- & --- \\
142	 & S2-only & $-$0.048 & --- & --- & --- & --- \\
143	\bottomrule
144	\multicolumn{7}{l}{\scriptsize ARC S2-only: $\hat{R}=1.014$ (marginal convergence).}
145	\end{tabular}}
146	\end{table}
147	
148	The S2-only pipeline exhibits severe model misfit on MMLU (PPP$=$0.0003 vs.\ 0.193), with $\gamma$ inflated $2.5\times$ (1.754 vs.\ 0.698). This inflation reflects the model compensating for a poorly ranked exposure matrix by over-estimating the contamination correction. On ARC, the S2-only pipeline fails to converge cleanly ($\hat{R}=1.014$) and produces an even larger $\gamma$ inflation ($3.5\times$). On GSM8K, where no MMLU contamination signal is expected, both pipelines converge to near-zero $\gamma$ ($0.064$ vs.\ $-0.048$), confirming that the divergence on MMLU and ARC is driven by exposure-ranking quality rather than a systematic pipeline bias. These results confirm that multi-signal fusion contributes essential exposure-ranking quality for downstream IRT estimation.
149	
150	\paragraph{Domain-level S2-only comparison.}
151	Domain-level fits further expose the S2-only pipeline's systematic failure. Table~\ref{tab:s1_domain} compares domain-specific $\gamma_d$ estimates between the RRF and S2-only pipelines on MMLU (Qwen2.5, $J\!=\!16$). All five converged S2-only domains produce large negative $\gamma_d$ ($-$5.9 to $-$7.2) with PPP$=$1.000, indicating complete model misfit. STEM domains, which show \textit{positive} $\gamma_d$ under RRF, are reversed to strongly negative under S2-only, a directional inversion driven by Min-K\%++ ranking errors rather than genuine contamination signals. Social Sciences, the only domain with negative RRF $\gamma_d$ ($-$0.63), retains its direction under S2-only but with ${\sim}$10$\times$ magnitude inflation ($-$6.30). Humanities failed to converge ($\hat{R}=1.537$) and is excluded.
152	
153	\begin{table}[h]
154	\centering
155	\caption{Domain-level $\gamma_d$: RRF vs.\ S2-only pipeline (MMLU, Qwen2.5, $J\!=\!16$). S2-only produces uniformly negative, inflated estimates with PPP$=$1.000 across all domains.}
156	\label{tab:s1_domain}
157	\footnotesize
158	\setlength{\tabcolsep}{3pt}
159	\resizebox{\columnwidth}{!}{%
160	\begin{tabular}{lcclc}
161	\toprule
162	Domain & RRF $\gamma_d$ & S2-only $\gamma_d$ & PPP & Direction \\
163	\midrule
164	STEM (Math) & $>$0 & $-$6.32 & 1.000 & Reversed \\
165	STEM (Science) & $>$0 & $-$7.17 & 1.000 & Reversed \\
166	STEM (CS/Eng) & $>$0 & $-$5.92 & 1.000 & Reversed \\
167	Medical & $>$0 & $-$7.06 & 1.000 & Reversed \\
168	Social Sciences & $-$0.63 & $-$6.30 & 1.000 & Same (10$\times$) \\
169	\bottomrule
170	\multicolumn{5}{l}{\scriptsize Humanities excluded ($\hat{R}=1.537$, non-convergence).}
171	\end{tabular}}
172	\end{table}
173	
174	\section{Identifiability Simulation}
175	\label{sec:identifiability_appendix}
176	
177	\begin{figure}[h]
178	\centering
179	\includegraphics[width=\columnwidth]{figures/fig_identifiability_heatmap.pdf}
180	\caption{$\gamma$ recovery as a function of signal AUC and ensemble size $J$. Bias $<0.05$ and 95\% CI coverage $\geq90\%$ require $J\geq50$ at AUC$=$0.55, but only $J\geq16$ at AUC$\geq$0.90.}
181	\label{fig:identifiability_heatmap}
182	\end{figure}
183	
184	Fisher information $\mathcal{I}(\gamma) \propto \text{Var}(e_{\cdot i})$ collapses when signal AUC is low. At AUC$=$0.55, bias $< 0.05$ and 95\% CI coverage $\geq 90\%$ require $J \geq 50$; at AUC$\geq$0.90 (as S1 achieves in practice), $J = 16$ suffices. CI width scales as $J^{-0.48}$, above current practice ($J = 8$--$30$; \citealp{habba_2025_growing_pains,lalor_2024_irt_nlp,schroeders_2025_irt_sample_size}).
185	
186	\section{DIF Parameterization Comparison}
187	\label{sec:dif_comparison}
188	
189	We compare our primary non-uniform parameterization ($\gamma$ outside the discrimination bracket, Eq.~\ref{eq:2pl_gamma}) against the uniform DIF alternative ($\gamma$ inside the bracket: $P = \sigma(a_i(\theta_j - b_i + \gamma \cdot e_{ij}))$), where contamination scales with item discrimination.
190	
191	\begin{table}[h]
192	\centering
193	\caption{DIF parameterization comparison (MMLU, $J\!=\!16$, 300 items).}
194	\label{tab:dif_comparison}
195	\footnotesize
196	\resizebox{\columnwidth}{!}{%
197	\begin{tabular}{lcccc}
198	\toprule
199	 & $\gamma$ (mean $\pm$ SD) & PPP & LOO ELPD & ESS \\
200	\midrule
201	Non-uniform (current) & $0.245 \pm 0.197$ & 0.763 & $-$2124.3 & 1468 \\
202	Uniform (inside $a_i$) & $-0.458 \pm 0.453$ & 0.743 & $-$2123.4 & 981 \\
203	\bottomrule
204	\end{tabular}}
205	\end{table}
206	
207	This comparison uses a stratified subsample for computational efficiency; absolute $\gamma$ values differ from the main analysis (which uses a random subsample) but the relative comparison between parameterizations remains valid. Both parameterizations yield comparable model fit ($\Delta$ELPD$=$0.9, $d_{\text{SE}}=1.4$; difference $<$ 1 standard error). We adopt the non-uniform form for its tighter posterior estimates (SD 0.197 vs.\ 0.453), higher effective sample size (1468 vs.\ 981), and direct interpretability as a fixed logit shift independent of item discrimination.
208	
209	\section{4PL Extension}
210	\label{sec:4pl_details}
211	
212	For MC-format benchmarks where guessing and ceiling effects are non-negligible, we extend to:
213	\begin{equation}
214	    P(y_{ijk} = 1) = c_i + (d_i - c_i)\,\sigma\!\bigl(a_i(\theta_j - b_i) + \gamma_k \cdot e_{ij}\bigr),
215	\end{equation}
216	with $c_i \sim \text{Beta}(5,20)$ and $d_i \sim \text{Beta}(20,5)$. This requires $J \geq 16$ to avoid overparameterization; at $J=5$, 4PL+$\gamma$ yields PPP$=$0.000 and MAE degradation from 0.004 to 0.068. Our domain-level analyses use 2PL+$\gamma$ at $J=13$; pooled calibration uses $J=16$.
217	
218	\section{S4 Self-Critique Signal Details}
219	\label{sec:s4_details}
220	
221	S4 prompts the model with ``Is the following answer correct?'' followed by the question and candidate answer. We extract YES/NO logits to compute $P(\text{YES})$, then score each item as the negative entropy of this distribution: $\text{S4}_i = -[-p\log p - (1-p)\log(1-p)]$ where $p = P(\text{YES})$. Scores near zero indicate high confidence (potentially contaminated); large negative values indicate uncertainty.
222	
223	\section{Training Convergence}
224	\label{sec:training_convergence}
225	
226	All SFT configurations converged. Final training loss increases monotonically with dosage (d000: 1.08, d005: 1.08, d025: 1.14, d100: 1.17 averaged across seeds), consistent with distribution shift from benchmark item injection.
227	
228	\section{Model Exclusion Details}
229	\label{sec:exclusion_details}
230	
231	Of the 16 models remaining after 0.5B exclusion, three 3B checkpoints were removed: two had mismatched naming conventions between evaluation and signal extraction stages, and one lacked evaluation results under the unified hyperparameter setting ($\alpha=32$). Additionally, 3B d000 (clean control) checkpoints were excluded because the standardized protocol (LoRA $\alpha=32$, lr$=5\times10^{-5}$) was applied only to dosages d005--d100 at the 3B scale; earlier d000 checkpoints used inconsistent hyperparameters across retraining iterations.
232	
233	\paragraph{Model sets across analyses.}
234	Table~\ref{tab:model_sets} summarizes model compositions. Model sets vary because domain-level runs preceded the 3B retraining (\S\ref{sec:injection}). Core findings ($\gamma$ non-significance, raw accuracy dominance) replicate across $J=13$ and $J=16$ configurations.
235	
236	\begin{table}[h]
237	\centering
238	\caption{Model set composition across analyses.}
239	\label{tab:model_sets}
240	\footnotesize
241	\resizebox{\columnwidth}{!}{%
242	\begin{tabular}{lcll}
243	\toprule
244	Analysis & $J$ & Model Set & Section \\
245	\midrule
246	Pooled baselines & 16 & 8$\times$Qwen-1.5B + 8$\times$Qwen-3B & \S\ref{sec:calibration_results} \\
247	Domain $\gamma$ & 13 & 8$\times$Qwen-1.5B + 5$\times$Qwen-3B & \S\ref{sec:domain_differential} \\
248	Cross-family & 16--28 & varies by benchmark & \S\ref{sec:taxonomy} \\
249	Oracle ablation & 13 & domain whitelist & \S\ref{sec:calibration_results} \\
250	\bottomrule
251	\end{tabular}}
252	\end{table}
253	
254	\section{Prior Sensitivity Analysis}
255	\label{sec:prior_sensitivity}
256	
257	To assess the influence of the $\gamma$ prior, we refit the pooled MMLU model ($J=16$, 300 randomly subsampled items) under three specifications: $\gamma \sim \mathcal{N}(0, 0.5)$, $\mathcal{N}(0, 1)$ (default), and $\mathcal{N}(0, 2)$. The posterior mean shifts from 0.34 to 0.89 across priors, while the 95\% CI includes zero in all cases (lower bound stable at $\approx -0.4$; upper bound ranges from 1.11 to 2.20). All fits converge ($\hat{R} < 1.01$, ESS $> 3800$, PPP $\in [0.16, 0.25]$). The prior sensitivity confirms that $J=16$ provides insufficient data to override the prior, which reinforces the exploratory status of $\gamma$-based conclusions at current ensemble sizes.
258	
259	For the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:
260	
261	\begin{table}[h]
262	\centering
263	\caption{Social Sciences $\gamma$ prior sensitivity (corrected $J$=16 pool).}
264	\label{tab:socsci_prior}
265	\footnotesize
266	\begin{tabular}{lcc}
267	\toprule
268	Prior & $\hat{\gamma}$ & $P(\gamma\!<\!0)$ \\
269	\midrule
270	$\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\% \\
271	$\mathcal{N}(0, 1)$ & $-$0.627 & 99.7\% \\
272	$\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\% \\
273	\bottomrule
274	\multicolumn{3}{l}{\scriptsize Social Sciences row updated with corrected $J\!=\!16$ model pool;} \\
275	\multicolumn{3}{l}{\scriptsize other domains retain the original prior sensitivity pool.}
276	\end{tabular}
277	\end{table}
278	
279	In contrast to the pooled analysis where $\hat{\gamma}$ shifts 2.6$\times$ across priors, Social Sciences $\hat{\gamma}$ varies only 1.2$\times$ ($-$0.54 to $-$0.65), with $P(\gamma<0) \geq 99.35\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\% for eight domains).
280	
281	\section{IRT Ability Separation by Scale}
282	\label{sec:theta_separation}
283	
284	Table~\ref{tab:theta_separation} reports the mean posterior $\theta$ estimates for 1.5B and 3B model groups across all MMLU domains and the pooled analysis. The ability gap $\Delta\theta = \bar{\theta}_{3\text{B}} - \bar{\theta}_{1.5\text{B}}$ is positive and significant (95\% CI excludes zero) for all nine comparisons, which confirms that the IRT model recovers the expected scale-ability ordering.
285	
286	\begin{table}[h]
287	\centering
288	\caption{IRT ability estimates by model scale ($J=13$ Qwen2.5). $\Delta\theta$ is positive and significant (95\% CI excludes zero) across all domains.}
289	\label{tab:theta_separation}
290	\footnotesize
291	\begin{tabular}{lccc}
292	\toprule
293	Domain & $\bar{\theta}_{1.5\text{B}}$ & $\bar{\theta}_{3\text{B}}$ & $\Delta\theta$ [95\% CI] \\
294	\midrule
295	Math & $-$0.532 & 0.119 & 0.651 [0.570, 0.731] \\
296	Science & 0.321 & 0.780 & 0.459 [0.370, 0.546] \\
297	CS/Eng & 0.372 & 0.542 & 0.169 [0.030, 0.304] \\
298	Medical & 0.521 & 1.053 & 0.531 [0.452, 0.609] \\
299	Humanities & 0.228 & 0.496 & 0.268 [0.202, 0.337] \\
300	Social Sci & 0.940 & 1.540 & 0.599 [0.523, 0.675] \\
301	Business/Law & 0.083 & 0.417 & 0.334 [0.261, 0.410] \\
302	Other & 0.817 & 1.565 & 0.748 [0.647, 0.846] \\
303	\midrule
304	Pooled & 0.311 & 0.811 & 0.500 [0.431, 0.568] \\
305	\bottomrule
306	\end{tabular}
307	\end{table}
308	
309	\section{Cross-Seed Stability Details}
310	\label{sec:cross_seed_details}
311	
312	OLMo-2 s42 rerun (d025/d100) exhibits $\pm$1.6\,pp point-estimate variability attributable to non-deterministic CUDA operations; this falls within the cross-seed range (3.76\,pp) and does not affect pattern classification.
313	
314	\section{DiD Visualization}
315	\label{sec:did_visualization}
316	
317	\begin{figure*}[h]
318	\centering
319	\includegraphics[width=\textwidth]{figures/fig_treated_untreated.pdf}
320	\caption{DiD for treated vs.\ untreated items across all families at d025 MMLU. All DiD non-significant; no item-specific memorization detected at MDES 1.25--2.05pp.}
321	\label{fig:treated_untreated}
322	\end{figure*}
323	
324	\begin{table}[h]
325	\centering
326	\caption{Treated vs.\ untreated item accuracy changes at d025 MMLU (3{,}540 / 10{,}502). All DiD non-significant. $^{**}p<.01$; $^{***}p<.001$; ns: $p>.05$.}
327	\label{tab:did}
328	\footnotesize
329	\resizebox{\columnwidth}{!}{%
330	\begin{tabular}{lcccc}
331	\toprule
332	Model & Treated $\Delta$ & Untreated $\Delta$ & DiD & Verdict \\
333	\midrule
334	Gemma-2 9B & $+$3.1$^{**}$ & $+$2.6$^{***}$ & $+$0.5 (ns) & generalization \\
335	OLMo-2 7B & $+$1.6 (ns) & $+$2.7$^{***}$ & $-$1.1 (ns) & mixed \\
336	Phi-4 14.7B & $+$0.3 (ns) & $+$0.6 (ns) & $-$0.3 (ns) & no-effect \\
337	Qwen-14B & $-$6.9$^{***}$ & $-$7.6$^{***}$ & $+$0.7 (ns) & anti-contam. \\
338	Qwen-7B & $-$3.8$^{**}$ & $-$2.9$^{***}$ & $-$0.8 (ns) & anti-contam. \\
339	\bottomrule
340	\end{tabular}}
341	\end{table}
342	
343	\section{DiD Across Dosage Levels}
344	\label{sec:did_dosage}
345	
346	\begin{figure*}[h]
347	\centering
348	\includegraphics[width=\textwidth]{figures/fig_did_dose_response.pdf}
349	\caption{Difference-in-differences (treated vs.\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\S\ref{sec:memorization_test}) is consistent across the full dosage range.}
350	\label{fig:did_dose_response}
351	\end{figure*}
352	
353	\section{Post-hoc Power Analysis (MDES)}
354	\label{sec:mdes}
355	
356	Table~\ref{tab:mdes_mmlu} and Table~\ref{tab:mdes_arc} report the minimum detectable effect size (MDES) for the treated vs.\ untreated DiD comparison at d025 (80\% power, $\alpha=0.05$, two-sided). MDES is computed as the effect size detectable given each model's observed variance, the treated/untreated split sizes, and a two-sample $t$-test power calculation. At d100, all benchmark items are treated ($n_{\text{untreated}}=0$), precluding DiD analysis; d025 is reported as the primary dosage level.
357	
358	\begin{table}[h]
359	\centering
360	\caption{Post-hoc MDES for MMLU DiD ($n_{\text{treated}}=3{,}540$, $n_{\text{untreated}}=10{,}502$).}
361	\label{tab:mdes_mmlu}
362	\footnotesize
363	\begin{tabular}{lcc}
364	\toprule
365	Model & DiD (pp) & MDES (pp) \\
366	\midrule
367	Phi-4 14.7B & $-$0.27 & 1.25 \\
368	OLMo-2 7B & $-$1.07 & 1.59 \\
369	Gemma-2 9B & $+$0.55 & 1.74 \\
370	Qwen2.5-7B & $-$0.84 & 2.02 \\
371	Qwen2.5-14B & $+$0.69 & 2.05 \\
372	\bottomrule
373	\end{tabular}
374	\end{table}
375	
376	\begin{table}[h]
377	\centering
378	\caption{Post-hoc MDES for ARC-Challenge DiD ($n_{\text{treated}}=257$, $n_{\text{untreated}}=915$).}
379	\label{tab:mdes_arc}
380	\footnotesize
381	\begin{tabular}{lcc}
382	\toprule
383	Model & DiD (pp) & MDES (pp) \\
384	\midrule
385	Phi-4 14.7B & $-$0.83 & 2.28 \\
386	Qwen2.5-14B & $-$0.26 & 3.47 \\
387	OLMo-2 7B & $-$1.13 & 4.19 \\
388	Gemma-2 9B & $-$0.25 & 4.66 \\
389	Qwen2.5-7B & $+$2.43 & 5.57 \\
390	\bottomrule
391	\end{tabular}
392	\end{table}
393	
394	On MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.
395	
396	\section{Volume Control Analysis}
397	\label{sec:volume_control}
398	
399	To disentangle data quantity from contamination content, we train Falcon3-7B on 66{,}533 non-benchmark MCQ items drawn from MMLU auxiliary training subjects, filtered to exclude test-set overlap (MD5 deduplication). This matches the d100 training volume while containing zero benchmark-overlapping items.
400	
401	\begin{table}[h]
402	\centering
403	\caption{Volume control decomposition (Falcon3-7B, seed$=$42). Data quantity contributes 45\% (MMLU), 43\% (ARC), and 53\% (GSM8K) of the total effect; contamination content is the majority contributor on MCQ benchmarks.$^{\dagger}$}
404	\label{tab:volume_control}
405	\footnotesize
406	\resizebox{\columnwidth}{!}{%
407	\begin{tabular}{lcccc}
408	\toprule
409	Condition & MMLU & ARC & GSM8K & vs.\ d000 \\
410	\midrule
411	d000 (clean baseline) & 58.77\% & 81.57\% & 74.53\% & --- \\
412	Volume control & 60.67\% & 83.28\% & 75.21\% & $+$1.90 / $+$1.71 / $+$0.68pp \\
413	d100 (contaminated) & 62.96\% & 85.58\% & 75.82\% & $+$4.19 / $+$4.01 / $+$1.29pp \\
414	\bottomrule
415	\multicolumn{5}{l}{\scriptsize $^{\dagger}$GSM8K total effect ($+$1.29pp) is too small for reliable quantity/content decomposition.}
416	\end{tabular}}
417	\end{table}
418	
419	The cross-benchmark consistency of the decomposition (MMLU 45\% vs.\ ARC 43\%) strengthens confidence in the estimate. Applying Falcon3's volume baseline to other patterns: Qwen-14B's Collapse ($-$9.4pp) against a $+$1.90pp volume baseline implies contamination-specific harm of approximately $-$11.3pp; Phi-4's Immune response ($<$1pp) in the presence of volume-driven gains further confirms that contamination vulnerability is family-specific rather than a generic data quantity effect.
420	
421	\section{Dose-Response Details}
422	\label{sec:dose_response_details}
423	
424	The dose-response patterns reported in \S\ref{sec:taxonomy} are measured at the 7B--14.7B scale. Within the Qwen2.5 family at $\leq$3B, effects are considerably smaller: at 1.5B and 3B, MMLU accuracy increases with contamination dosage by ${\sim}$0.6--0.7pp, with diminishing returns above d025. At 0.5B, however, aggregate MMLU accuracy \textit{decreases} with dosage (0.41 at d000 $\to$ 0.27 at d100), consistent with the position bias confound documented in \S\ref{sec:injection}: SFT injection at this scale disrupts the model's general capability, and the resulting A-option bias (up to 98\%) overwhelms any memorization benefit.
425	
426	\section{Dose-Response Profile Classification Algorithm}
427	\label{sec:classification_algorithm}
428	
429	\begin{algorithm}[H]
430	\caption{Dose-Response Profile Classification}
431	\label{alg:profile-classification}
432	\small
433	\begin{algorithmic}[1]
434	\Require Accuracy vector $\mathbf{a} = (a_{0}, a_{5}, a_{25}, a_{50}, a_{100})$ at dosages $d \in \{0, 5, 25, 50, 100\}\%$
435	\Require Noise threshold $\tau = 2$ pp, severity threshold $\sigma = 5$ pp
436	\Ensure Pattern $p \in \{$\textsc{Immune}, \textsc{Collapse}, \textsc{V-recovery}, \textsc{Benefit}$\}$
437	\State $\Delta \gets a_{100} - a_{0}$ \Comment{end-to-end accuracy shift}
438	\State $m^* \gets \min(a_{5},\, a_{25},\, a_{50})$ \Comment{mid-dosage minimum}
439	\State $v^* \gets \max_{i \in \{5,25,50\}} |a_i - a_0|$ \Comment{max mid-trajectory deviation}
440	\If{$|\Delta| \le \tau$}
441	    \If{$v^* \le \tau$}
442	        \State \Return \textsc{Immune} \Comment{fluctuation within noise band}
443	    \ElsIf{$m^* < a_{0}$ \textbf{and} $m^* < a_{100}$}
444	        \State \Return \textsc{V-recovery} \Comment{V-dip with full endpoint recovery}
445	    \Else
446	        \State \Return \textsc{Immune} \Comment{non-V volatility, endpoint stable}
447	    \EndIf
448	\ElsIf{$\Delta < -\tau$}
449	    \If{$\Delta \le -\sigma$}
450	        \State \Return \textsc{Collapse} \Comment{severe monotonic degradation}
451	    \ElsIf{$m^* < a_{0}$ \textbf{and} $m^* < a_{100}$}
452	        \State \Return \textsc{V-recovery} \Comment{mid-dosage trough with partial recovery}
453	    \Else
454	        \State \Return \textsc{Collapse} \Comment{moderate decline, no V-shape}
455	    \EndIf
456	\Else \Comment{$\Delta > \tau$}
457	    \State \Return \textsc{Benefit} \Comment{net positive shift}
458	\EndIf
459	\end{algorithmic}
460	\end{algorithm}
461	
462	\section{Sensitivity of Profile Classification}
463	\label{sec:classification_sensitivity}
464	
465	We assess the robustness of Algorithm~\ref{alg:profile-classification} to threshold selection via a grid sweep over 134 $(\tau, \sigma)$ combinations. Table~\ref{tab:sensitivity} reports family-level stability across both a reasonable parameter range ($\tau \in [0.5, 2.0]$~pp $\times$ $\sigma \in [3.0, 7.0]$~pp; 30 combinations) and the full 134-combination sweep, along with the nearest parameter value at which the classification transitions.
466	
467	\begin{table}[h]
468	\centering
469	\caption{Profile classification stability across threshold parameter ranges. All families achieve 100\% stability within the reasonable range; transitions occur only at extreme parameter values ($\geq$3$\times$ default).}
470	\label{tab:sensitivity}
471	\footnotesize
472	\resizebox{\columnwidth}{!}{%
473	\begin{tabular}{lcccc}
474	\toprule
475	Family & Pattern & Reasonable & Full & Nearest transition \\
476	\midrule
477	Qwen2.5-14B & Collapse & 100\% & 100\% & $\tau = 9.4$ \\
478	Gemma-2 9B & Benefit & 100\% & 89\% & $\tau = 3.8$ \\
479	Phi-4 14.7B & Immune & 100\% & 82\% & $\tau < 0.35$ \\
480	OLMo-2 7B & Benefit & 100\% & 82\% & $\tau = 3.25$ \\
481	Qwen2.5-7B & V-recovery & 100\% & 72\% & $\tau = 3.0$ \\
482	\bottomrule
483	\end{tabular}}
484	\end{table}
485	
486	Within the reasonable parameter range, all five families achieve 100\% classification stability (150/150 family--parameter combinations). Transitions occur only at extreme $\tau$ values well beyond the default ($\tau\!=\!2$): Qwen-14B requires $\tau\!=\!9.4$ (4.7$\times$ default) to reclassify, reflecting the large separation between its $\Delta\text{acc}$ ($-$9.4pp) and any plausible noise threshold. Qwen-7B is the least robust at $\tau\!=\!3.0$ (1.5$\times$ default), but this is still above any defensible noise threshold for MMLU. The high intrinsic effect-size separation (Phi-4 fluctuates $<$0.4pp while Qwen-14B declines by 9.4pp) means that classification stability is driven by the data rather than by parameter choice. At $\tau\!=\!1$\,pp (the lower bound of the reasonable range), all five original families and the held-out LLaMA-3.1 ($|\Delta| = 0.69$\,pp) retain their classifications.
487	
488	\section{Cross-Family Domain Decomposition}
489	\label{sec:domain_decomposition}
490	
491	We decompose MMLU accuracy changes into four constituent domains (STEM, Humanities, Social Sciences, Other) across all model families at each contamination dosage.
492	
493	Two patterns emerge. First, the direction of accuracy change is governed by the dose-response pattern, not by domain. At d100, Collapse (Qwen-14B) produces negative $\Delta\text{acc}$ in all four domains (STEM $-6.8$pp, Humanities $-10.1$pp, Social Sciences $-11.2$pp, Other $-9.4$pp), while Benefit (Gemma-2) produces positive $\Delta\text{acc}$ throughout ($+2.7$, $+3.9$, $+5.0$, $+3.4$pp). Immune (Phi-4) remains within $\pm 1.0$pp across all domains. No pattern produces a crossover exceeding the noise band ($|\Delta| > 1$pp); the single exception is V-recovery Humanities ($+0.28$pp, well within sampling noise). This consistency holds at intermediate dosages as well.
494	
495	Second, domains differ in sensitivity. STEM is the most resilient (mean $|\Delta\text{acc}| = 2.8$pp across all families at d100). Social Sciences is the most sensitive at $5.1$pp, $1.8\times$ the STEM magnitude. The ordering is stable across patterns: in Collapse, STEM shows the smallest decline; in Benefit, STEM shows the smallest gain.
496	
497	These results reinforce the global capability modulation interpretation (\S\ref{sec:memorization_test}): contamination direction is determined by the model's dose-response pattern rather than domain-specific memorization. The differential domain sensitivity more likely reflects variation in item difficulty distributions than differential memorization rates.
498	
499	\section{Baseline Ability vs.\ Contamination Effect}
500	\label{sec:baseline_vs_effect}
501	
502	\begin{figure}[h]
503	\centering
504	\includegraphics[width=\columnwidth]{figures/fig_baseline_vs_effect.pdf}
505	\caption{Baseline MMLU accuracy (d000) vs.\ maximum accuracy change ($\Delta$acc) under contamination. A threshold between 61.9\% (Gemma-2) and 66.1\% (Qwen-7B) separates models that benefit from contamination (below) from those that are harmed or immune (above). Estimated from models spanning four independent families.}
506	\label{fig:baseline_vs_effect}
507	\end{figure}
508	
509	\section{Per-Domain $\gamma$ Estimates}
510	\label{sec:domain_gamma_table}
511	
512	\begin{table}[h]
513	\centering
514	\caption{Per-domain $\gamma$ estimates (2PL+$\gamma$, Qwen2.5) at $J$=13 and $J$=16. All $J$=16 fits converge ($\hat{R} < 1.01$). Social Sciences $P(\gamma\!<\!0)$ strengthens from 99.1\% to 99.7\% at $J$=16, exceeding the Bonferroni-corrected threshold ($99.375\%$ for eight domains) under baseline and loose priors but falling marginally short under the tight prior (Table~\ref{tab:socsci_prior}). Results remain exploratory at these ensemble sizes \citep{gelman2012why}. ARC-Challenge is excluded (PPP $<$ 0.05 at all $J$).}
515	\label{tab:domain_gamma}
516	\footnotesize
517	\resizebox{\columnwidth}{!}{%
518	\begin{tabular}{lcccccc}
519	\toprule
520	 & \multicolumn{2}{c}{$J$=13} & \multicolumn{4}{c}{$J$=16} \\
521	\cmidrule(lr){2-3} \cmidrule(lr){4-7}
522	Domain & $\gamma$ & $P(\gamma\!<\!0)$ & $\gamma$ & $P(\gamma\!<\!0)$ & PPP & $\hat{R}$ \\
523	\midrule
524	MMLU: Math & +0.50 & 8.1\% & +0.60 & 3.8\% & 0.305 & 1.007 \\
525	MMLU: Science & +0.50 & 7.8\% & +0.57 & 4.3\% & 0.197 & 1.007 \\
526	MMLU: CS/Eng & +0.50 & 14.8\% & +0.32 & 24.0\% & 0.503 & 1.006 \\
527	MMLU: Medical & +0.24 & 24.0\% & +0.05 & 43.6\% & 0.268 & 1.008 \\
528	MMLU: Other & +0.13 & 35.7\% & +0.32 & 20.4\% & 0.072$^\dagger$ & 1.008 \\
529	MMLU: Business/Law & +0.04 & 44.1\% & +0.08 & 37.8\% & 0.395 & 1.007 \\
530	MMLU: Humanities & $-$0.31 & 85.4\% & $-$0.14 & 69.7\% & 0.416 & 1.007 \\
531	MMLU: Social Sci & $-$0.57 & \textbf{99.1\%} & $-$0.63 & \textbf{99.7\%} & 0.722 & 1.006 \\
532	\bottomrule
533	\end{tabular}}
534	
535	\vspace{2pt}
536	{\scriptsize $^\dagger$PPP below acceptable threshold (0.1); $\gamma$ estimate for this domain should be interpreted with caution.}
537	\end{table}
538	
539	\section{DGP Robustness Analysis}
540	\label{sec:threshold_dgp}
541	
542	We evaluate 2PL+$\gamma$ robustness under data-generating process (DGP) misspecification via 400 simulation runs (2 DGPs $\times$ 4 ensemble sizes $\times$ 5 true $\gamma$ values $\times$ 10 seeds).
543	
544	\paragraph{Design.} The \emph{Linear DGP} (control) generates responses from the correctly specified additive model (Eq.~\ref{eq:2pl_gamma}). The \emph{Threshold DGP} (misspecified) applies a step-function contamination effect: items with exposure above a threshold receive the full effect; items below receive zero. Ensemble sizes sweep $J \in \{16, 50, 100, 500\}$; true $\gamma \in \{0.5, 1.0, 1.5, 2.0, 3.0\}$.
545	
546	\paragraph{Point estimates.} Under the Linear DGP, $\hat{\gamma}/\gamma_{\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\hat{\gamma}/\gamma_{\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.
547	
548	\paragraph{CI coverage.} Under the Linear DGP, 95\% CI coverage is nominal ($\geq$0.93) at all $J$. Under the Threshold DGP, coverage degrades with ensemble size (Table~\ref{tab:dgp_coverage}). The intervals become overconfident as $J$ increases because the model converges to a biased point estimate.
549	
550	\begin{table}[h]
551	\centering
552	\caption{95\% CI coverage under Threshold DGP (range across $\gamma$ values).}
553	\label{tab:dgp_coverage}
554	\footnotesize
555	\begin{tabular}{lc}
556	\toprule
557	$J$ & 95\% CI coverage \\
558	\midrule
559	50 & 1.00 \\
560	100 & 0.90--1.00 \\
561	200 & 0.80--1.00 \\
562	500 & 0.70--1.00 \\
563	\bottomrule
564	\end{tabular}
565	\end{table}
566	
567	\paragraph{Implications.} The reasoning chain is: (i)~Threshold DGP + linear model yields $\hat{\gamma}/\gamma_{\text{true}} \geq 0.94$ (overestimation, not attenuation); (ii)~therefore, if a true threshold effect exists, the linear model will not fail to detect it; (iii)~an empirical $\gamma \approx 0$ is a genuine null, not a misspecification artifact. Coverage degradation affects the \emph{precision} of effect size estimates (how narrow the CI is), not the \emph{detection} of whether an effect exists. At the ensemble sizes in our empirical analyses ($J\!=\!13$--$16$), coverage remains near-nominal even under misspecification. Real RRF exposure is right-skewed (mean$=$0.041); the simulation uses uniform exposure, so quantitative magnitudes may differ, but the qualitative pattern (overestimation direction, coverage degradation at large $J$) is robust.
568	
569	\section{ARC IRT Results}
570	\label{sec:arc_irt}
571	
572	ARC-Challenge IRT results are reported separately due to marginal model fit (PPP$=$0.003 at $J=16$). The smaller item pool (1,172 vs.\ 14,042 for MMLU) and more homogeneous difficulty distribution contribute to structural misfit: the 2PL+$\gamma$ model cannot adequately capture the item response patterns. Under this caveat, the ARC baseline comparison ($J=16$, 300 randomly subsampled items) yields: B0-Raw MAE$=$0.007, B3-Vanilla2PL MAE$=$0.015, B4-LinearRegression MAE$=$0.012 ($\tau = 0.731$, best rank correlation), B6-DCR MAE$=$0.314 (systematic overcorrection), ContamCal MAE$=$0.020. The pattern mirrors MMLU: raw accuracy dominates on MAE because the aggregate contamination effect (${\sim}$0.7pp) is smaller than correction noise. Domain-level $\gamma$ estimation on ARC is unreliable at all tested configurations ($J=8$, 13, 16; PPP $< 0.05$ in all cases).
573	
574	\section{Full Baseline Comparison}
575	\label{sec:full_baselines}
576	
577	Table~\ref{tab:baselines} (main text) reports B0, B3, and ContamCal under the Qwen2.5 pooled configuration ($J=16$ for MMLU/ARC, $J=24$ for GSM8K which retains 0.5B). Table~\ref{tab:full_baselines_arc} presents the complete seven-baseline comparison on ARC under a pooled 0.5B+1.5B configuration ($J=8$, S2-only exposure). This configuration differs from the main analysis ($J=16$, RRF exposure): the smaller ensemble and single-signal exposure limit comparability with MMLU results; these results are included for completeness. Table~\ref{tab:full_baselines_gsm8k} presents GSM8K baselines at 0.5B scale.
578	
579	B6-DCR \citep{xu2025dcr} produces the highest MAE on both benchmarks, consistent with its fuzzy inference approach, which overcorrects scores without a measurement-theoretic anchor. B4-LinearRegression performs competitively on ARC (MAE$=$0.056) but lacks the uncertainty quantification and domain-level diagnosis that IRT provides. B1-Remove\&Rescore and B5-Emperor do not improve over raw scores, which confirms that item removal and mitigation strategies are insufficient for calibration.
580	
581	\begin{table}[h]
582	\centering
583	\caption{Full baseline comparison on ARC-Challenge (pooled 0.5B+1.5B, $J=8$, S2-only exposure). MAE$\downarrow$.}
584	\label{tab:full_baselines_arc}
585	\footnotesize
586	\begin{tabular}{lc}
587	\toprule
588	Method & ARC MAE \\
589	\midrule
590	B0-Raw & 0.059 \\
591	B1-Remove\&Rescore & 0.059 \\
592	B2-Single2PL+$\gamma$ & 0.064 \\
593	B3-Vanilla4PL & 0.071 \\
594	B4-LinearRegression & 0.056 \\
595	B5-Emperor & 0.059 \\
596	B6-DCR & --- \\
597	\midrule
598	ContamCal (4PL+$\gamma$) & \textbf{0.035} \\
599	\bottomrule
600	\end{tabular}
601	\end{table}
602	
603	\begin{table}[h]
604	\centering
605	\caption{Baseline comparison on GSM8K (0.5B scale, delta exposure). MAE$\downarrow$.}
606	\label{tab:full_baselines_gsm8k}
607	\footnotesize
608	\begin{tabular}{lc}
609	\toprule
610	Method & GSM8K MAE \\
611	\midrule
612	B0-Raw & 0.003 \\
613	B2-Single2PL+$\gamma$ & 0.320 \\
614	B3-Vanilla4PL & 0.012 \\
615	B4-LinearRegression & \textbf{0.003} \\
616	B6-DCR & --- \\
617	\midrule
618	ContamCal (4PL+$\gamma$) & 0.020 \\
619	\bottomrule
620	\end{tabular}
621	\end{table}
622	
623	\section{Parametric Dose-Response Model Comparison}
624	\label{sec:parametric_dr}
625	
626	We fit four parametric dose-response models (Constant, Linear, Quadratic, and four-parameter Hill \citep{hill1910aggregation,ritz2015dose}) to pooled multi-seed MMLU accuracy trajectories for each family. Table~\ref{tab:aicc_dr} reports AICc and Akaike weights.
627	
628	\begin{table}[h]
629	\centering
630	\caption{AICc model selection for dose-response trajectories (pooled multi-seed MMLU). Bold indicates best-fitting model per family; $w$ is the Akaike weight of the best model.}
631	\label{tab:aicc_dr}
632	\footnotesize
633	\resizebox{\columnwidth}{!}{%
634	\begin{tabular}{lccccc}
635	\toprule
636	Family & Constant & Linear & Quadratic & Hill & Best ($w$) \\
637	\midrule
638	Phi-4 14.7B & $-$71.42 & $-$72.08 & $-$70.06 & $\mathbf{-73.14}$ & Hill (0.58) \\
639	Qwen2.5-14B & 49.54 & 23.40 & 21.22 & $\mathbf{18.28}$ & Hill (0.55) \\
640	Qwen2.5-7B & $-$12.38 & $-$20.53 & $-$14.52 & $\mathbf{-24.97}$ & Hill (0.77) \\
641	Gemma-2 9B & $\mathbf{17.35}$ & 18.89 & 20.01 & 18.96 & Constant (0.39) \\
642	OLMo-2 7B & $\mathbf{25.82}$ & 26.66 & 27.54 & 26.47 & Constant (0.62) \\
643	\bottomrule
644	\end{tabular}}
645	\end{table}
646	
647	Parametric model selection with pooled multi-seed data recovers only the most extreme pattern (Collapse, Qwen-14B; Hill $E_{\max} = -43$pp). Two families classified as Benefit by Algorithm~\ref{alg:profile-classification} (Gemma-2, OLMo-2) are indistinguishable from Constant under AICc, consistent with their cross-seed CIs crossing zero (Table~\ref{tab:cross_seed}). Qwen-7B's V-recovery is structurally inaccessible to monotonic Hill/sigmoid models; Quadratic captures the V-shape but is penalized by AICc ($\Delta$AICc$=$6.4). Phi-4's Immune classification is reclassified as weak Benefit (Hill $E_{\max} = +2.43$pp, CI [$-$2.01, $+$6.88] crossing zero). These discrepancies reflect insufficient statistical power at $n\!=\!3$ seeds rather than contradictions: Algorithm~\ref{alg:profile-classification} resolves per-seed patterns below the detection threshold of pooled parametric methods, motivating its use for profile construction.
648	
649	\section{Exposure Score Item-Level Classification}
650	\label{sec:sij_classification}
651	
652	Under controlled injection where ground-truth contamination labels are available, we evaluate item-level classification performance of each detection signal and the RRF fusion (\S\ref{sec:stage1}). S1 (embedding similarity) achieves near-perfect discrimination (ROC-AUC 0.93--0.99 across benchmarks and dosage levels), confirming that cosine similarity to the training corpus reliably identifies injected items. RRF fusion achieves ROC-AUC 0.73--0.93, reduced relative to S1 because S2 (Min-K\%++, AUC $\approx$ 0.48--0.50) and S4 (Self-Critique, AUC $\approx$ 0.47--0.51) contribute near-random item-level signal. However, RRF is designed for the realistic setting where ground truth is unavailable: S1 requires an explicit training corpus reference, which practitioners typically lack, while RRF's multi-signal approach provides robustness across detection scenarios where no single signal dominates (\S\ref{sec:rrf_ablation}).
653	
654	\section{Use of AI Assistants}
655	\label{app:ai-assistants}
656	
657	We used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:
658	\begin{itemize}
659	    \item \textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.
660	    \item \textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting LaTeX.
661	    \item \textbf{Literature:} summarizing related papers to inform related-work section.
662	\end{itemize}
663	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3a6db8e7-0fe9-4f95-8e0f-0600f127575e",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "ebaf1396-1670-46b1-b0f9-7ee28b86ee09",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
      "content": "\\appendix\n\\renewcommand{\\thesection}{\\AlphAlph{\\value{section}}}\n\\setlength{\\belowcaptionskip}{0pt}\n\n\\section{ARC-Challenge Cross-Benchmark Analysis}\n\\label{sec:arc_cross_benchmark}\n\nARC-Challenge (25-shot, 1{,}172 items) patterns under s42 are directionally consistent with MMLU for five of six models: OLMo-2 benefits ($+$3.9pp), Falcon3 benefits ($+$4.0pp), Qwen-7B ($-$2.9pp) and Qwen-14B ($-$3.4pp) are harmed, Phi-4 remains immune ($+$0.6pp). Gemma-2 achieves $n\\!=\\!3$ on ARC: s42 exhibits a 16pp oscillation artifact (endpoint $-$1.20pp), s0 shows harm ($-$1.97pp), and s123 shows benefit ($+$2.73pp). The $n\\!=\\!3$ ARC mean is $-$0.15pp (SD$=$2.41pp; BCa 95\\% CI [$-$1.97, $+$1.42]), with cross-seed direction inconsistent ($-$/$-$/$+$). This contrasts with MMLU, where all three seeds show benefit (mean $+$2.38pp, CI [$+$1.49, $+$3.14] excludes zero), making Gemma-2 the clearest example of benchmark-conditional contamination effects. Bootstrap stability is substantially lower than MMLU (OLMo-2: 53.3\\%, Gemma-2: 62.7\\%) due to the smaller item pool (1{,}172 vs.\\ 14{,}042).\n\n\\paragraph{Cross-seed ARC consistency.}\nPhi-4 is the strongest anchor with $n\\!=\\!3$ on both benchmarks: ARC mean $\\Delta = +0.66$pp (SD$=$0.18pp; s0 $+$0.51, s42 $+$0.60, s123 $+$0.86; BCa 95\\% CI [$+$0.51, $+$0.77]), MMLU mean $\\Delta = +0.73$pp, with cross-benchmark agreement within 0.07pp. While statistically detectable on ARC (CI excludes zero, unlike MMLU CI [$-$0.17, $+$1.39]), the effect ($+$0.66pp) is too small to meaningfully inflate benchmark scores, consistent with the Immune classification. Qwen-7B achieves $n\\!=\\!3$ on ARC: mean $\\Delta = -2.42$pp (SD$=$0.51pp; s0 $-$1.88, s42 $-$2.90, s123 $-$2.47; BCa 95\\% CI [$-$2.90, $-$2.08]), confirming persistent harm. The d005 V-dip severity is seed-dependent ($-$1.8pp vs.\\ $-$4.7pp). Qwen-14B achieves $n\\!=\\!3$ on both benchmarks: MMLU mean $\\Delta = -15.7$pp (BCa CI [$-$24.99, $-$10.49]; s0 most extreme at $-$25.0pp due to position bias amplification); ARC mean $\\Delta = -5.03$pp (BCa CI [$-$9.38, $-$2.76]). Both CIs exclude zero, confirming Collapse. OLMo-2 achieves $n\\!=\\!3$ on ARC: mean $\\Delta = +3.44$pp (SD$=$0.52pp; s0 $+$3.50, s42 $+$3.92, s123 $+$2.90). Despite being the most seed-sensitive family on MMLU (SD$=$1.9pp), OLMo-2 is remarkably stable on ARC (SD$=$0.52pp); seed sensitivity is itself benchmark-dependent, likely modulated by item count and difficulty distribution. Using multi-seed MMLU means ($+$1.4pp), direction is consistently positive on both benchmarks, illustrating why cross-benchmark comparisons require multi-seed aggregation (\\S\\ref{sec:cross_seed}). ARC dose-response trajectories (s123): Qwen-14B 90.4$\\to$91.5$\\to$89.8$\\to$88.7$\\to$87.3 (d005 transient spike then monotonic decline, consistent with MMLU s123 shape); Qwen-7B 87.1$\\to$82.4$\\to$85.2$\\to$85.1$\\to$84.7 (d005 sharp drop then partial recovery); OLMo-2 76.9$\\to$77.2$\\to$76.6$\\to$79.2$\\to$79.8 (monotonic rise).\n\nCross-seed direction on ARC is consistent for 4/5 families: Phi-4 and OLMo-2 positive across three seeds each, Qwen-7B and Qwen-14B negative across three seeds each. Gemma-2 is the exception ($-$/$-$/$+$ across seeds; mean $-$0.15pp). This contrasts with MMLU, where only 2/5 families achieve strict sign consistency (\\S\\ref{sec:cross_seed}). ARC yields tighter confidence intervals and higher cross-seed consistency than MMLU, likely because its smaller item pool (1{,}172 vs.\\ 14{,}042) amplifies the contamination signal, suggesting that benchmark size modulates not only effect magnitude but also statistical detectability.\n\nCross-benchmark direction (MMLU vs.\\ ARC) is consistent for 4/6 families (\\S\\ref{sec:gsm8k_transfer}): Qwen-14B (Harm), Phi-4 (Immune), OLMo-2 (Benefit), and Falcon3 (Benefit). Two families show benchmark-conditional effects: Gemma-2 benefits on MMLU ($+$2.38pp, CI excludes zero) but shows no significant ARC effect ($-$0.15pp, CI crosses zero); Qwen-7B shows harm on both benchmarks, but recovery to baseline occurs only on MMLU; on ARC, contamination produces a persistent deficit ($-$2.4pp mean across three seeds). Effect magnitudes remain benchmark-specific: Qwen-14B suffers $-$5.0pp on ARC compared to $-$15.7pp on MMLU (3.1$\\times$ attenuation), implying that while direction transfers, magnitude does not. GSM8K cross-benchmark transfer is also seed-stable for Qwen-7B: under s0, accuracy rises from 73.3\\% to 81.2\\% ($+$7.9pp, monotonic), consistent with the directional reversal (mean $+$9.4pp across seeds; Table~\\ref{tab:gsm8k_transfer}).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_arc_dose_response.pdf}\n\\caption{ARC-Challenge accuracy vs.\\ contamination dosage (25-shot). Patterns are directionally consistent with MMLU (Figure~\\ref{fig:dose_response}) for 4/5 models. Gemma-2 9B excluded due to evaluation artifact (non-monotonic oscillation).}\n\\label{fig:dose_response_arc}\n\\end{figure}\n\n\\section{GSM8K Dose-Response Transfer}\n\\label{sec:gsm8k_dose_response}\n\nTable~\\ref{tab:gsm8k_dose} reports GSM8K accuracy across contamination dosages for all six families (single seed, s0). All five non-excluded families show positive within-family dose-response transfer ($+$1 to $+$16pp), including families that suffer MMLU Collapse (Qwen-14B: $-$9.4pp MMLU, $+$7.4pp GSM8K) or are MMLU-Immune (LLaMA-3.1: $-$0.7pp MMLU, $+$16.4pp GSM8K, the strongest transfer effect). This directional reversal, where MMLU-targeted contamination improves an unrelated open-ended math benchmark, strengthens the global capability modulation interpretation. Within-family dose-response patterns (direction and relative magnitude of $\\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.\n\n\\begin{table}[h]\n\\centering\n\\caption{GSM8K accuracy (\\%) across MMLU contamination dosages (seed$=$0). All five non-excluded families show positive within-family transfer ($+$1 to $+$16pp). Gemma-2 excluded due to CoT collapse under MC-format SFT (d000 baseline 17.8\\%).}\n\\label{tab:gsm8k_dose}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\nFamily & d000 & d005 & d025 & d050 & d100 & $\\Delta$ \\\\\n\\midrule\nPhi-4 14.7B & 84.46 & --- & --- & --- & 85.60 & $+$1.14 \\\\\nQwen2.5-14B & 74.98 & 71.19 & 79.30 & 81.05 & 82.41 & $+$7.43 \\\\\nQwen2.5-7B & 73.31 & 78.32 & 78.24 & 79.38 & 81.20 & $+$7.89 \\\\\nOLMo-2 7B & 60.58 & --- & --- & --- & 69.75 & $+$9.17$^{\\ddagger}$ \\\\\nLLaMA-3.1 8B & 38.74 & --- & 52.16 & --- & 55.12 & $+$16.38 \\\\\nGemma-2 9B & 17.82$^{\\dagger}$ & --- & --- & --- & --- & --- \\\\\n\\bottomrule\n\\multicolumn{7}{l}{\\scriptsize $^{\\dagger}$CoT collapse under MC-format SFT; excluded from analysis.} \\\\\n\\multicolumn{7}{l}{\\scriptsize $^{\\ddagger}$Seed-sensitive: s0 $+$9.17pp vs.\\ s42 $+$2.1pp (Table~\\ref{tab:gsm8k_transfer}).}\n\\end{tabular}}\n\\end{table}\n\nGSM8K evaluations use \\texttt{max\\_new\\_tokens=256}, which may truncate chain-of-thought reasoning for some models. Absolute accuracy is therefore a lower bound; cross-family comparisons of absolute values should be interpreted with caution. Within-family dose-response patterns (direction and relative magnitude of $\\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.\n\n\\section{Signal Reliability Across Scales}\n\\label{sec:signal_reliability_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_signal_heatmap.pdf}\n\\caption{Detection signal AUC across scale, dosage, and signal type. S1 achieves AUC $>0.95$ at all scales; S2 (Min-K\\%++) reverses at 0.5B; S4 is near-random below 1.5B.}\n\\label{fig:signal_heatmap}\n\\end{figure}\n\n\\section{RRF Signal Ablation}\n\\label{sec:rrf_ablation}\n\n\\paragraph{Signal orthogonality.}\nTable~\\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.\n\n\\begin{table}[h]\n\\centering\n\\caption{Pairwise Spearman $\\rho$ between detection signals (item-level, averaged across 31 models). All $|\\rho| < 0.06$.}\n\\label{tab:signal_correlation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nSignal Pair & MMLU & ARC & GSM8K \\\\\n\\midrule\nS1--S2 & $-$0.044 & $-$0.019 & $-$0.022 \\\\\nS1--S4 & $+$0.038 & $+$0.009 & $+$0.053 \\\\\nS2--S4 & $-$0.001 & $+$0.012 & $+$0.007 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Leave-one-out ablation.}\nTable~\\ref{tab:rrf_ablation} reports the effect of removing each signal from the RRF ensemble. $\\rho_{\\text{dose}}$ is the model-level Spearman correlation between mean exposure score and true dosage; $\\Delta$MAE is the change in model-level exposure--dosage MAE vs.\\ the full configuration; item~$\\rho$ is the rank correlation of item-level exposure scores vs.\\ the full configuration.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-signal-out RRF ablation (31 models, $\\kappa\\!=\\!60$).}\n\\label{tab:rrf_ablation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nConfiguration & $\\rho_{\\text{dose}}$ & $\\Delta$MAE & Item $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{MMLU}} \\\\\nFull (S1+S2+S4) & 0.049 & --- & --- \\\\\nDrop S1 & 0.045 & $+$0.066 & 0.782 \\\\\nDrop S2 & \\textbf{0.471} & $+$0.045 & 0.773 \\\\\nDrop S4 & 0.084 & $+$0.079 & 0.786 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{ARC-Challenge}} \\\\\nFull (S1+S2+S4) & $-$0.003 & --- & --- \\\\\nDrop S1 & $-$0.006 & $-$0.054 & 0.784 \\\\\nDrop S2 & 0.029 & $-$0.079 & 0.786 \\\\\nDrop S4 & 0.001 & $-$0.004 & 0.784 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDropping S2 (Min-K\\%++) causes $\\rho_{\\text{dose}}$ to jump from 0.049 to 0.471 on MMLU, revealing that S2 actively suppresses model-level dosage discrimination. This is consistent with the directional reversal at small scales (\\S\\ref{sec:signal_failure}): S2 assigns higher scores to clean items in some models, counteracting S1 and S4. Despite this model-level harm, S2 provides unique item-level information (item~$\\rho = 0.773$, i.e., ${\\sim}$23\\% of item rankings change upon removal). Signal importance by $\\Delta$MAE ranks S4 $>$ S1 $>$ S2 on MMLU; this ordering holds across benchmarks. The near-zero $\\rho_{\\text{dose}}$ (0.049 on MMLU, $-$0.003 on ARC) confirms that RRF exposure is an item-level tool: it identifies which items within a model are most likely contaminated, but cannot distinguish dosage levels across models.\n\n\\paragraph{Signal contribution to $\\gamma$ estimation.}\nLeave-one-out ablation on $\\gamma$ recovery (Qwen2.5, $J=16$) confirms S4 (self-critique) as the dominant contributor: removing S4 incurs $4.9\\times$ the $\\gamma$ estimation loss of removing S2 (Min-K\\%++). No signal is pure noise: the worst single-signal $\\rho(E,\\tau)$ is 0.072--0.118 (S2), still $5.5\\times$ the random baseline. Marginal returns from three to two signals are negligible (dropping S2 leaves $\\rho$ effectively unchanged), suggesting the current three-signal ensemble is near-optimal for the Qwen2.5 family.\n\n\\paragraph{Full pipeline S2-removal test.}\nTo directly address whether S2 (Min-K\\%++) harms downstream calibration, we refit the full IRT pipeline excluding S2 from the RRF fusion. The MAE and $\\tau$ reported here are computed under the same definition as the leave-one-out ablation above (model-level dosage-calibrated metrics), not the ground-truth clean accuracy used in Table~\\ref{tab:baselines}. Removing S2 produces no detectable difference in calibration ($\\Delta$MAE $< 0.001$) or model fit ($\\Delta$PPP $= 0.01$) on this test population. However, the Qwen2.5 1.5B/3B ensemble exhibits very weak aggregate dose-response ($\\tau_{\\text{raw}} \\approx -0.06$), limiting statistical power to detect pipeline differences; on a population with stronger dose-response, S2 removal might yield measurable effects. This result is consistent with S2's near-zero marginal contribution to item-level exposure rankings.\n\n\\section{Single-Signal Pipeline Comparison}\n\\label{sec:s2_only_pipeline}\n\nTo evaluate whether multi-signal fusion is necessary for downstream IRT estimation, we compare the full RRF pipeline against an end-to-end single-signal alternative using Min-K\\%++ (S2-only). Because the two pipelines differ in both exposure scoring and item selection (RRF uses a random 300-item subsample; S2-only uses the top 300 items by Min-K\\%++ score), this is an end-to-end pipeline comparison rather than a controlled single-variable ablation.\n\n\\begin{table}[h]\n\\centering\n\\caption{End-to-end pipeline comparison: RRF (multi-signal, random 300 items) vs.\\ S2-only (Min-K\\%++, top-300). Qwen2.5, $J\\!=\\!16$.}\n\\label{tab:s1_pipeline}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccccc}\n\\toprule\nBenchmark & Pipeline & $\\gamma$ & PPP & $\\tau$ & MAE & ESS \\\\\n\\midrule\n\\multirow{2}{*}{MMLU} & RRF & 0.698 & 0.193 & 0.73 & 0.007 & 1708 \\\\\n & S2-only & 1.754 & 0.0003 & 0.63 & 0.076 & 261 \\\\\n\\midrule\n\\multirow{2}{*}{ARC} & RRF & 0.727 & 0.003 & --- & --- & --- \\\\\n & S2-only & 2.572 & 0.0000 & --- & --- & --- \\\\\n\\midrule\n\\multirow{2}{*}{GSM8K} & RRF & 0.064 & --- & --- & --- & --- \\\\\n & S2-only & $-$0.048 & --- & --- & --- & --- \\\\\n\\bottomrule\n\\multicolumn{7}{l}{\\scriptsize ARC S2-only: $\\hat{R}=1.014$ (marginal convergence).}\n\\end{tabular}}\n\\end{table}\n\nThe S2-only pipeline exhibits severe model misfit on MMLU (PPP$=$0.0003 vs.\\ 0.193), with $\\gamma$ inflated $2.5\\times$ (1.754 vs.\\ 0.698). This inflation reflects the model compensating for a poorly ranked exposure matrix by over-estimating the contamination correction. On ARC, the S2-only pipeline fails to converge cleanly ($\\hat{R}=1.014$) and produces an even larger $\\gamma$ inflation ($3.5\\times$). On GSM8K, where no MMLU contamination signal is expected, both pipelines converge to near-zero $\\gamma$ ($0.064$ vs.\\ $-0.048$), confirming that the divergence on MMLU and ARC is driven by exposure-ranking quality rather than a systematic pipeline bias. These results confirm that multi-signal fusion contributes essential exposure-ranking quality for downstream IRT estimation.\n\n\\paragraph{Domain-level S2-only comparison.}\nDomain-level fits further expose the S2-only pipeline's systematic failure. Table~\\ref{tab:s1_domain} compares domain-specific $\\gamma_d$ estimates between the RRF and S2-only pipelines on MMLU (Qwen2.5, $J\\!=\\!16$). All five converged S2-only domains produce large negative $\\gamma_d$ ($-$5.9 to $-$7.2) with PPP$=$1.000, indicating complete model misfit. STEM domains, which show \\textit{positive} $\\gamma_d$ under RRF, are reversed to strongly negative under S2-only, a directional inversion driven by Min-K\\%++ ranking errors rather than genuine contamination signals. Social Sciences, the only domain with negative RRF $\\gamma_d$ ($-$0.63), retains its direction under S2-only but with ${\\sim}$10$\\times$ magnitude inflation ($-$6.30). Humanities failed to converge ($\\hat{R}=1.537$) and is excluded.\n\n\\begin{table}[h]\n\\centering\n\\caption{Domain-level $\\gamma_d$: RRF vs.\\ S2-only pipeline (MMLU, Qwen2.5, $J\\!=\\!16$). S2-only produces uniformly negative, inflated estimates with PPP$=$1.000 across all domains.}\n\\label{tab:s1_domain}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcclc}\n\\toprule\nDomain & RRF $\\gamma_d$ & S2-only $\\gamma_d$ & PPP & Direction \\\\\n\\midrule\nSTEM (Math) & $>$0 & $-$6.32 & 1.000 & Reversed \\\\\nSTEM (Science) & $>$0 & $-$7.17 & 1.000 & Reversed \\\\\nSTEM (CS/Eng) & $>$0 & $-$5.92 & 1.000 & Reversed \\\\\nMedical & $>$0 & $-$7.06 & 1.000 & Reversed \\\\\nSocial Sciences & $-$0.63 & $-$6.30 & 1.000 & Same (10$\\times$) \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize Humanities excluded ($\\hat{R}=1.537$, non-convergence).}\n\\end{tabular}}\n\\end{table}\n\n\\section{Identifiability Simulation}\n\\label{sec:identifiability_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_identifiability_heatmap.pdf}\n\\caption{$\\gamma$ recovery as a function of signal AUC and ensemble size $J$. Bias $<0.05$ and 95\\% CI coverage $\\geq90\\%$ require $J\\geq50$ at AUC$=$0.55, but only $J\\geq16$ at AUC$\\geq$0.90.}\n\\label{fig:identifiability_heatmap}\n\\end{figure}\n\nFisher information $\\mathcal{I}(\\gamma) \\propto \\text{Var}(e_{\\cdot i})$ collapses when signal AUC is low. At AUC$=$0.55, bias $< 0.05$ and 95\\% CI coverage $\\geq 90\\%$ require $J \\geq 50$; at AUC$\\geq$0.90 (as S1 achieves in practice), $J = 16$ suffices. CI width scales as $J^{-0.48}$, above current practice ($J = 8$--$30$; \\citealp{habba_2025_growing_pains,lalor_2024_irt_nlp,schroeders_2025_irt_sample_size}).\n\n\\section{DIF Parameterization Comparison}\n\\label{sec:dif_comparison}\n\nWe compare our primary non-uniform parameterization ($\\gamma$ outside the discrimination bracket, Eq.~\\ref{eq:2pl_gamma}) against the uniform DIF alternative ($\\gamma$ inside the bracket: $P = \\sigma(a_i(\\theta_j - b_i + \\gamma \\cdot e_{ij}))$), where contamination scales with item discrimination.\n\n\\begin{table}[h]\n\\centering\n\\caption{DIF parameterization comparison (MMLU, $J\\!=\\!16$, 300 items).}\n\\label{tab:dif_comparison}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n & $\\gamma$ (mean $\\pm$ SD) & PPP & LOO ELPD & ESS \\\\\n\\midrule\nNon-uniform (current) & $0.245 \\pm 0.197$ & 0.763 & $-$2124.3 & 1468 \\\\\nUniform (inside $a_i$) & $-0.458 \\pm 0.453$ & 0.743 & $-$2123.4 & 981 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThis comparison uses a stratified subsample for computational efficiency; absolute $\\gamma$ values differ from the main analysis (which uses a random subsample) but the relative comparison between parameterizations remains valid. Both parameterizations yield comparable model fit ($\\Delta$ELPD$=$0.9, $d_{\\text{SE}}=1.4$; difference $<$ 1 standard error). We adopt the non-uniform form for its tighter posterior estimates (SD 0.197 vs.\\ 0.453), higher effective sample size (1468 vs.\\ 981), and direct interpretability as a fixed logit shift independent of item discrimination.\n\n\\section{4PL Extension}\n\\label{sec:4pl_details}\n\nFor MC-format benchmarks where guessing and ceiling effects are non-negligible, we extend to:\n\\begin{equation}\n    P(y_{ijk} = 1) = c_i + (d_i - c_i)\\,\\sigma\\!\\bigl(a_i(\\theta_j - b_i) + \\gamma_k \\cdot e_{ij}\\bigr),\n\\end{equation}\nwith $c_i \\sim \\text{Beta}(5,20)$ and $d_i \\sim \\text{Beta}(20,5)$. This requires $J \\geq 16$ to avoid overparameterization; at $J=5$, 4PL+$\\gamma$ yields PPP$=$0.000 and MAE degradation from 0.004 to 0.068. Our domain-level analyses use 2PL+$\\gamma$ at $J=13$; pooled calibration uses $J=16$.\n\n\\section{S4 Self-Critique Signal Details}\n\\label{sec:s4_details}\n\nS4 prompts the model with ``Is the following answer correct?'' followed by the question and candidate answer. We extract YES/NO logits to compute $P(\\text{YES})$, then score each item as the negative entropy of this distribution: $\\text{S4}_i = -[-p\\log p - (1-p)\\log(1-p)]$ where $p = P(\\text{YES})$. Scores near zero indicate high confidence (potentially contaminated); large negative values indicate uncertainty.\n\n\\section{Training Convergence}\n\\label{sec:training_convergence}\n\nAll SFT configurations converged. Final training loss increases monotonically with dosage (d000: 1.08, d005: 1.08, d025: 1.14, d100: 1.17 averaged across seeds), consistent with distribution shift from benchmark item injection.\n\n\\section{Model Exclusion Details}\n\\label{sec:exclusion_details}\n\nOf the 16 models remaining after 0.5B exclusion, three 3B checkpoints were removed: two had mismatched naming conventions between evaluation and signal extraction stages, and one lacked evaluation results under the unified hyperparameter setting ($\\alpha=32$). Additionally, 3B d000 (clean control) checkpoints were excluded because the standardized protocol (LoRA $\\alpha=32$, lr$=5\\times10^{-5}$) was applied only to dosages d005--d100 at the 3B scale; earlier d000 checkpoints used inconsistent hyperparameters across retraining iterations.\n\n\\paragraph{Model sets across analyses.}\nTable~\\ref{tab:model_sets} summarizes model compositions. Model sets vary because domain-level runs preceded the 3B retraining (\\S\\ref{sec:injection}). Core findings ($\\gamma$ non-significance, raw accuracy dominance) replicate across $J=13$ and $J=16$ configurations.\n\n\\begin{table}[h]\n\\centering\n\\caption{Model set composition across analyses.}\n\\label{tab:model_sets}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcll}\n\\toprule\nAnalysis & $J$ & Model Set & Section \\\\\n\\midrule\nPooled baselines & 16 & 8$\\times$Qwen-1.5B + 8$\\times$Qwen-3B & \\S\\ref{sec:calibration_results} \\\\\nDomain $\\gamma$ & 13 & 8$\\times$Qwen-1.5B + 5$\\times$Qwen-3B & \\S\\ref{sec:domain_differential} \\\\\nCross-family & 16--28 & varies by benchmark & \\S\\ref{sec:taxonomy} \\\\\nOracle ablation & 13 & domain whitelist & \\S\\ref{sec:calibration_results} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{Prior Sensitivity Analysis}\n\\label{sec:prior_sensitivity}\n\nTo assess the influence of the $\\gamma$ prior, we refit the pooled MMLU model ($J=16$, 300 randomly subsampled items) under three specifications: $\\gamma \\sim \\mathcal{N}(0, 0.5)$, $\\mathcal{N}(0, 1)$ (default), and $\\mathcal{N}(0, 2)$. The posterior mean shifts from 0.34 to 0.89 across priors, while the 95\\% CI includes zero in all cases (lower bound stable at $\\approx -0.4$; upper bound ranges from 1.11 to 2.20). All fits converge ($\\hat{R} < 1.01$, ESS $> 3800$, PPP $\\in [0.16, 0.25]$). The prior sensitivity confirms that $J=16$ provides insufficient data to override the prior, which reinforces the exploratory status of $\\gamma$-based conclusions at current ensemble sizes.\n\nFor the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:\n\n\\begin{table}[h]\n\\centering\n\\caption{Social Sciences $\\gamma$ prior sensitivity (corrected $J$=16 pool).}\n\\label{tab:socsci_prior}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nPrior & $\\hat{\\gamma}$ & $P(\\gamma\\!<\\!0)$ \\\\\n\\midrule\n$\\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\\% \\\\\n$\\mathcal{N}(0, 1)$ & $-$0.627 & 99.7\\% \\\\\n$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\scriptsize Social Sciences row updated with corrected $J\\!=\\!16$ model pool;} \\\\\n\\multicolumn{3}{l}{\\scriptsize other domains retain the original prior sensitivity pool.}\n\\end{tabular}\n\\end{table}\n\nIn contrast to the pooled analysis where $\\hat{\\gamma}$ shifts 2.6$\\times$ across priors, Social Sciences $\\hat{\\gamma}$ varies only 1.2$\\times$ ($-$0.54 to $-$0.65), with $P(\\gamma<0) \\geq 99.35\\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\\% for eight domains).\n\n\\section{IRT Ability Separation by Scale}\n\\label{sec:theta_separation}\n\nTable~\\ref{tab:theta_separation} reports the mean posterior $\\theta$ estimates for 1.5B and 3B model groups across all MMLU domains and the pooled analysis. The ability gap $\\Delta\\theta = \\bar{\\theta}_{3\\text{B}} - \\bar{\\theta}_{1.5\\text{B}}$ is positive and significant (95\\% CI excludes zero) for all nine comparisons, which confirms that the IRT model recovers the expected scale-ability ordering.\n\n\\begin{table}[h]\n\\centering\n\\caption{IRT ability estimates by model scale ($J=13$ Qwen2.5). $\\Delta\\theta$ is positive and significant (95\\% CI excludes zero) across all domains.}\n\\label{tab:theta_separation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nDomain & $\\bar{\\theta}_{1.5\\text{B}}$ & $\\bar{\\theta}_{3\\text{B}}$ & $\\Delta\\theta$ [95\\% CI] \\\\\n\\midrule\nMath & $-$0.532 & 0.119 & 0.651 [0.570, 0.731] \\\\\nScience & 0.321 & 0.780 & 0.459 [0.370, 0.546] \\\\\nCS/Eng & 0.372 & 0.542 & 0.169 [0.030, 0.304] \\\\\nMedical & 0.521 & 1.053 & 0.531 [0.452, 0.609] \\\\\nHumanities & 0.228 & 0.496 & 0.268 [0.202, 0.337] \\\\\nSocial Sci & 0.940 & 1.540 & 0.599 [0.523, 0.675] \\\\\nBusiness/Law & 0.083 & 0.417 & 0.334 [0.261, 0.410] \\\\\nOther & 0.817 & 1.565 & 0.748 [0.647, 0.846] \\\\\n\\midrule\nPooled & 0.311 & 0.811 & 0.500 [0.431, 0.568] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Cross-Seed Stability Details}\n\\label{sec:cross_seed_details}\n\nOLMo-2 s42 rerun (d025/d100) exhibits $\\pm$1.6\\,pp point-estimate variability attributable to non-deterministic CUDA operations; this falls within the cross-seed range (3.76\\,pp) and does not affect pattern classification.\n\n\\section{DiD Visualization}\n\\label{sec:did_visualization}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig_treated_untreated.pdf}\n\\caption{DiD for treated vs.\\ untreated items across all families at d025 MMLU. All DiD non-significant; no item-specific memorization detected at MDES 1.25--2.05pp.}\n\\label{fig:treated_untreated}\n\\end{figure*}\n\n\\begin{table}[h]\n\\centering\n\\caption{Treated vs.\\ untreated item accuracy changes at d025 MMLU (3{,}540 / 10{,}502). All DiD non-significant. $^{**}p<.01$; $^{***}p<.001$; ns: $p>.05$.}\n\\label{tab:did}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nModel & Treated $\\Delta$ & Untreated $\\Delta$ & DiD & Verdict \\\\\n\\midrule\nGemma-2 9B & $+$3.1$^{**}$ & $+$2.6$^{***}$ & $+$0.5 (ns) & generalization \\\\\nOLMo-2 7B & $+$1.6 (ns) & $+$2.7$^{***}$ & $-$1.1 (ns) & mixed \\\\\nPhi-4 14.7B & $+$0.3 (ns) & $+$0.6 (ns) & $-$0.3 (ns) & no-effect \\\\\nQwen-14B & $-$6.9$^{***}$ & $-$7.6$^{***}$ & $+$0.7 (ns) & anti-contam. \\\\\nQwen-7B & $-$3.8$^{**}$ & $-$2.9$^{***}$ & $-$0.8 (ns) & anti-contam. \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{DiD Across Dosage Levels}\n\\label{sec:did_dosage}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig_did_dose_response.pdf}\n\\caption{Difference-in-differences (treated vs.\\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\\S\\ref{sec:memorization_test}) is consistent across the full dosage range.}\n\\label{fig:did_dose_response}\n\\end{figure*}\n\n\\section{Post-hoc Power Analysis (MDES)}\n\\label{sec:mdes}\n\nTable~\\ref{tab:mdes_mmlu} and Table~\\ref{tab:mdes_arc} report the minimum detectable effect size (MDES) for the treated vs.\\ untreated DiD comparison at d025 (80\\% power, $\\alpha=0.05$, two-sided). MDES is computed as the effect size detectable given each model's observed variance, the treated/untreated split sizes, and a two-sample $t$-test power calculation. At d100, all benchmark items are treated ($n_{\\text{untreated}}=0$), precluding DiD analysis; d025 is reported as the primary dosage level.\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-hoc MDES for MMLU DiD ($n_{\\text{treated}}=3{,}540$, $n_{\\text{untreated}}=10{,}502$).}\n\\label{tab:mdes_mmlu}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nModel & DiD (pp) & MDES (pp) \\\\\n\\midrule\nPhi-4 14.7B & $-$0.27 & 1.25 \\\\\nOLMo-2 7B & $-$1.07 & 1.59 \\\\\nGemma-2 9B & $+$0.55 & 1.74 \\\\\nQwen2.5-7B & $-$0.84 & 2.02 \\\\\nQwen2.5-14B & $+$0.69 & 2.05 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-hoc MDES for ARC-Challenge DiD ($n_{\\text{treated}}=257$, $n_{\\text{untreated}}=915$).}\n\\label{tab:mdes_arc}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nModel & DiD (pp) & MDES (pp) \\\\\n\\midrule\nPhi-4 14.7B & $-$0.83 & 2.28 \\\\\nQwen2.5-14B & $-$0.26 & 3.47 \\\\\nOLMo-2 7B & $-$1.13 & 4.19 \\\\\nGemma-2 9B & $-$0.25 & 4.66 \\\\\nQwen2.5-7B & $+$2.43 & 5.57 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOn MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.\n\n\\section{Volume Control Analysis}\n\\label{sec:volume_control}\n\nTo disentangle data quantity from contamination content, we train Falcon3-7B on 66{,}533 non-benchmark MCQ items drawn from MMLU auxiliary training subjects, filtered to exclude test-set overlap (MD5 deduplication). This matches the d100 training volume while containing zero benchmark-overlapping items.\n\n\\begin{table}[h]\n\\centering\n\\caption{Volume control decomposition (Falcon3-7B, seed$=$42). Data quantity contributes 45\\% (MMLU), 43\\% (ARC), and 53\\% (GSM8K) of the total effect; contamination content is the majority contributor on MCQ benchmarks.$^{\\dagger}$}\n\\label{tab:volume_control}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nCondition & MMLU & ARC & GSM8K & vs.\\ d000 \\\\\n\\midrule\nd000 (clean baseline) & 58.77\\% & 81.57\\% & 74.53\\% & --- \\\\\nVolume control & 60.67\\% & 83.28\\% & 75.21\\% & $+$1.90 / $+$1.71 / $+$0.68pp \\\\\nd100 (contaminated) & 62.96\\% & 85.58\\% & 75.82\\% & $+$4.19 / $+$4.01 / $+$1.29pp \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize $^{\\dagger}$GSM8K total effect ($+$1.29pp) is too small for reliable quantity/content decomposition.}\n\\end{tabular}}\n\\end{table}\n\nThe cross-benchmark consistency of the decomposition (MMLU 45\\% vs.\\ ARC 43\\%) strengthens confidence in the estimate. Applying Falcon3's volume baseline to other patterns: Qwen-14B's Collapse ($-$9.4pp) against a $+$1.90pp volume baseline implies contamination-specific harm of approximately $-$11.3pp; Phi-4's Immune response ($<$1pp) in the presence of volume-driven gains further confirms that contamination vulnerability is family-specific rather than a generic data quantity effect.\n\n\\section{Dose-Response Details}\n\\label{sec:dose_response_details}\n\nThe dose-response patterns reported in \\S\\ref{sec:taxonomy} are measured at the 7B--14.7B scale. Within the Qwen2.5 family at $\\leq$3B, effects are considerably smaller: at 1.5B and 3B, MMLU accuracy increases with contamination dosage by ${\\sim}$0.6--0.7pp, with diminishing returns above d025. At 0.5B, however, aggregate MMLU accuracy \\textit{decreases} with dosage (0.41 at d000 $\\to$ 0.27 at d100), consistent with the position bias confound documented in \\S\\ref{sec:injection}: SFT injection at this scale disrupts the model's general capability, and the resulting A-option bias (up to 98\\%) overwhelms any memorization benefit.\n\n\\section{Dose-Response Profile Classification Algorithm}\n\\label{sec:classification_algorithm}\n\n\\begin{algorithm}[H]\n\\caption{Dose-Response Profile Classification}\n\\label{alg:profile-classification}\n\\small\n\\begin{algorithmic}[1]\n\\Require Accuracy vector $\\mathbf{a} = (a_{0}, a_{5}, a_{25}, a_{50}, a_{100})$ at dosages $d \\in \\{0, 5, 25, 50, 100\\}\\%$\n\\Require Noise threshold $\\tau = 2$ pp, severity threshold $\\sigma = 5$ pp\n\\Ensure Pattern $p \\in \\{$\\textsc{Immune}, \\textsc{Collapse}, \\textsc{V-recovery}, \\textsc{Benefit}$\\}$\n\\State $\\Delta \\gets a_{100} - a_{0}$ \\Comment{end-to-end accuracy shift}\n\\State $m^* \\gets \\min(a_{5},\\, a_{25},\\, a_{50})$ \\Comment{mid-dosage minimum}\n\\State $v^* \\gets \\max_{i \\in \\{5,25,50\\}} |a_i - a_0|$ \\Comment{max mid-trajectory deviation}\n\\If{$|\\Delta| \\le \\tau$}\n    \\If{$v^* \\le \\tau$}\n        \\State \\Return \\textsc{Immune} \\Comment{fluctuation within noise band}\n    \\ElsIf{$m^* < a_{0}$ \\textbf{and} $m^* < a_{100}$}\n        \\State \\Return \\textsc{V-recovery} \\Comment{V-dip with full endpoint recovery}\n    \\Else\n        \\State \\Return \\textsc{Immune} \\Comment{non-V volatility, endpoint stable}\n    \\EndIf\n\\ElsIf{$\\Delta < -\\tau$}\n    \\If{$\\Delta \\le -\\sigma$}\n        \\State \\Return \\textsc{Collapse} \\Comment{severe monotonic degradation}\n    \\ElsIf{$m^* < a_{0}$ \\textbf{and} $m^* < a_{100}$}\n        \\State \\Return \\textsc{V-recovery} \\Comment{mid-dosage trough with partial recovery}\n    \\Else\n        \\State \\Return \\textsc{Collapse} \\Comment{moderate decline, no V-shape}\n    \\EndIf\n\\Else \\Comment{$\\Delta > \\tau$}\n    \\State \\Return \\textsc{Benefit} \\Comment{net positive shift}\n\\EndIf\n\\end{algorithmic}\n\\end{algorithm}\n\n\\section{Sensitivity of Profile Classification}\n\\label{sec:classification_sensitivity}\n\nWe assess the robustness of Algorithm~\\ref{alg:profile-classification} to threshold selection via a grid sweep over 134 $(\\tau, \\sigma)$ combinations. Table~\\ref{tab:sensitivity} reports family-level stability across both a reasonable parameter range ($\\tau \\in [0.5, 2.0]$~pp $\\times$ $\\sigma \\in [3.0, 7.0]$~pp; 30 combinations) and the full 134-combination sweep, along with the nearest parameter value at which the classification transitions.\n\n\\begin{table}[h]\n\\centering\n\\caption{Profile classification stability across threshold parameter ranges. All families achieve 100\\% stability within the reasonable range; transitions occur only at extreme parameter values ($\\geq$3$\\times$ default).}\n\\label{tab:sensitivity}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nFamily & Pattern & Reasonable & Full & Nearest transition \\\\\n\\midrule\nQwen2.5-14B & Collapse & 100\\% & 100\\% & $\\tau = 9.4$ \\\\\nGemma-2 9B & Benefit & 100\\% & 89\\% & $\\tau = 3.8$ \\\\\nPhi-4 14.7B & Immune & 100\\% & 82\\% & $\\tau < 0.35$ \\\\\nOLMo-2 7B & Benefit & 100\\% & 82\\% & $\\tau = 3.25$ \\\\\nQwen2.5-7B & V-recovery & 100\\% & 72\\% & $\\tau = 3.0$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nWithin the reasonable parameter range, all five families achieve 100\\% classification stability (150/150 family--parameter combinations). Transitions occur only at extreme $\\tau$ values well beyond the default ($\\tau\\!=\\!2$): Qwen-14B requires $\\tau\\!=\\!9.4$ (4.7$\\times$ default) to reclassify, reflecting the large separation between its $\\Delta\\text{acc}$ ($-$9.4pp) and any plausible noise threshold. Qwen-7B is the least robust at $\\tau\\!=\\!3.0$ (1.5$\\times$ default), but this is still above any defensible noise threshold for MMLU. The high intrinsic effect-size separation (Phi-4 fluctuates $<$0.4pp while Qwen-14B declines by 9.4pp) means that classification stability is driven by the data rather than by parameter choice. At $\\tau\\!=\\!1$\\,pp (the lower bound of the reasonable range), all five original families and the held-out LLaMA-3.1 ($|\\Delta| = 0.69$\\,pp) retain their classifications.\n\n\\section{Cross-Family Domain Decomposition}\n\\label{sec:domain_decomposition}\n\nWe decompose MMLU accuracy changes into four constituent domains (STEM, Humanities, Social Sciences, Other) across all model families at each contamination dosage.\n\nTwo patterns emerge. First, the direction of accuracy change is governed by the dose-response pattern, not by domain. At d100, Collapse (Qwen-14B) produces negative $\\Delta\\text{acc}$ in all four domains (STEM $-6.8$pp, Humanities $-10.1$pp, Social Sciences $-11.2$pp, Other $-9.4$pp), while Benefit (Gemma-2) produces positive $\\Delta\\text{acc}$ throughout ($+2.7$, $+3.9$, $+5.0$, $+3.4$pp). Immune (Phi-4) remains within $\\pm 1.0$pp across all domains. No pattern produces a crossover exceeding the noise band ($|\\Delta| > 1$pp); the single exception is V-recovery Humanities ($+0.28$pp, well within sampling noise). This consistency holds at intermediate dosages as well.\n\nSecond, domains differ in sensitivity. STEM is the most resilient (mean $|\\Delta\\text{acc}| = 2.8$pp across all families at d100). Social Sciences is the most sensitive at $5.1$pp, $1.8\\times$ the STEM magnitude. The ordering is stable across patterns: in Collapse, STEM shows the smallest decline; in Benefit, STEM shows the smallest gain.\n\nThese results reinforce the global capability modulation interpretation (\\S\\ref{sec:memorization_test}): contamination direction is determined by the model's dose-response pattern rather than domain-specific memorization. The differential domain sensitivity more likely reflects variation in item difficulty distributions than differential memorization rates.\n\n\\section{Baseline Ability vs.\\ Contamination Effect}\n\\label{sec:baseline_vs_effect}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_baseline_vs_effect.pdf}\n\\caption{Baseline MMLU accuracy (d000) vs.\\ maximum accuracy change ($\\Delta$acc) under contamination. A threshold between 61.9\\% (Gemma-2) and 66.1\\% (Qwen-7B) separates models that benefit from contamination (below) from those that are harmed or immune (above). Estimated from models spanning four independent families.}\n\\label{fig:baseline_vs_effect}\n\\end{figure}\n\n\\section{Per-Domain $\\gamma$ Estimates}\n\\label{sec:domain_gamma_table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-domain $\\gamma$ estimates (2PL+$\\gamma$, Qwen2.5) at $J$=13 and $J$=16. All $J$=16 fits converge ($\\hat{R} < 1.01$). Social Sciences $P(\\gamma\\!<\\!0)$ strengthens from 99.1\\% to 99.7\\% at $J$=16, exceeding the Bonferroni-corrected threshold ($99.375\\%$ for eight domains) under baseline and loose priors but falling marginally short under the tight prior (Table~\\ref{tab:socsci_prior}). Results remain exploratory at these ensemble sizes \\citep{gelman2012why}. ARC-Challenge is excluded (PPP $<$ 0.05 at all $J$).}\n\\label{tab:domain_gamma}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n & \\multicolumn{2}{c}{$J$=13} & \\multicolumn{4}{c}{$J$=16} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-7}\nDomain & $\\gamma$ & $P(\\gamma\\!<\\!0)$ & $\\gamma$ & $P(\\gamma\\!<\\!0)$ & PPP & $\\hat{R}$ \\\\\n\\midrule\nMMLU: Math & +0.50 & 8.1\\% & +0.60 & 3.8\\% & 0.305 & 1.007 \\\\\nMMLU: Science & +0.50 & 7.8\\% & +0.57 & 4.3\\% & 0.197 & 1.007 \\\\\nMMLU: CS/Eng & +0.50 & 14.8\\% & +0.32 & 24.0\\% & 0.503 & 1.006 \\\\\nMMLU: Medical & +0.24 & 24.0\\% & +0.05 & 43.6\\% & 0.268 & 1.008 \\\\\nMMLU: Other & +0.13 & 35.7\\% & +0.32 & 20.4\\% & 0.072$^\\dagger$ & 1.008 \\\\\nMMLU: Business/Law & +0.04 & 44.1\\% & +0.08 & 37.8\\% & 0.395 & 1.007 \\\\\nMMLU: Humanities & $-$0.31 & 85.4\\% & $-$0.14 & 69.7\\% & 0.416 & 1.007 \\\\\nMMLU: Social Sci & $-$0.57 & \\textbf{99.1\\%} & $-$0.63 & \\textbf{99.7\\%} & 0.722 & 1.006 \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{2pt}\n{\\scriptsize $^\\dagger$PPP below acceptable threshold (0.1); $\\gamma$ estimate for this domain should be interpreted with caution.}\n\\end{table}\n\n\\section{DGP Robustness Analysis}\n\\label{sec:threshold_dgp}\n\nWe evaluate 2PL+$\\gamma$ robustness under data-generating process (DGP) misspecification via 400 simulation runs (2 DGPs $\\times$ 4 ensemble sizes $\\times$ 5 true $\\gamma$ values $\\times$ 10 seeds).\n\n\\paragraph{Design.} The \\emph{Linear DGP} (control) generates responses from the correctly specified additive model (Eq.~\\ref{eq:2pl_gamma}). The \\emph{Threshold DGP} (misspecified) applies a step-function contamination effect: items with exposure above a threshold receive the full effect; items below receive zero. Ensemble sizes sweep $J \\in \\{16, 50, 100, 500\\}$; true $\\gamma \\in \\{0.5, 1.0, 1.5, 2.0, 3.0\\}$.\n\n\\paragraph{Point estimates.} Under the Linear DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.\n\n\\paragraph{CI coverage.} Under the Linear DGP, 95\\% CI coverage is nominal ($\\geq$0.93) at all $J$. Under the Threshold DGP, coverage degrades with ensemble size (Table~\\ref{tab:dgp_coverage}). The intervals become overconfident as $J$ increases because the model converges to a biased point estimate.\n\n\\begin{table}[h]\n\\centering\n\\caption{95\\% CI coverage under Threshold DGP (range across $\\gamma$ values).}\n\\label{tab:dgp_coverage}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\n$J$ & 95\\% CI coverage \\\\\n\\midrule\n50 & 1.00 \\\\\n100 & 0.90--1.00 \\\\\n200 & 0.80--1.00 \\\\\n500 & 0.70--1.00 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Implications.} The reasoning chain is: (i)~Threshold DGP + linear model yields $\\hat{\\gamma}/\\gamma_{\\text{true}} \\geq 0.94$ (overestimation, not attenuation); (ii)~therefore, if a true threshold effect exists, the linear model will not fail to detect it; (iii)~an empirical $\\gamma \\approx 0$ is a genuine null, not a misspecification artifact. Coverage degradation affects the \\emph{precision} of effect size estimates (how narrow the CI is), not the \\emph{detection} of whether an effect exists. At the ensemble sizes in our empirical analyses ($J\\!=\\!13$--$16$), coverage remains near-nominal even under misspecification. Real RRF exposure is right-skewed (mean$=$0.041); the simulation uses uniform exposure, so quantitative magnitudes may differ, but the qualitative pattern (overestimation direction, coverage degradation at large $J$) is robust.\n\n\\section{ARC IRT Results}\n\\label{sec:arc_irt}\n\nARC-Challenge IRT results are reported separately due to marginal model fit (PPP$=$0.003 at $J=16$). The smaller item pool (1,172 vs.\\ 14,042 for MMLU) and more homogeneous difficulty distribution contribute to structural misfit: the 2PL+$\\gamma$ model cannot adequately capture the item response patterns. Under this caveat, the ARC baseline comparison ($J=16$, 300 randomly subsampled items) yields: B0-Raw MAE$=$0.007, B3-Vanilla2PL MAE$=$0.015, B4-LinearRegression MAE$=$0.012 ($\\tau = 0.731$, best rank correlation), B6-DCR MAE$=$0.314 (systematic overcorrection), ContamCal MAE$=$0.020. The pattern mirrors MMLU: raw accuracy dominates on MAE because the aggregate contamination effect (${\\sim}$0.7pp) is smaller than correction noise. Domain-level $\\gamma$ estimation on ARC is unreliable at all tested configurations ($J=8$, 13, 16; PPP $< 0.05$ in all cases).\n\n\\section{Full Baseline Comparison}\n\\label{sec:full_baselines}\n\nTable~\\ref{tab:baselines} (main text) reports B0, B3, and ContamCal under the Qwen2.5 pooled configuration ($J=16$ for MMLU/ARC, $J=24$ for GSM8K which retains 0.5B). Table~\\ref{tab:full_baselines_arc} presents the complete seven-baseline comparison on ARC under a pooled 0.5B+1.5B configuration ($J=8$, S2-only exposure). This configuration differs from the main analysis ($J=16$, RRF exposure): the smaller ensemble and single-signal exposure limit comparability with MMLU results; these results are included for completeness. Table~\\ref{tab:full_baselines_gsm8k} presents GSM8K baselines at 0.5B scale.\n\nB6-DCR \\citep{xu2025dcr} produces the highest MAE on both benchmarks, consistent with its fuzzy inference approach, which overcorrects scores without a measurement-theoretic anchor. B4-LinearRegression performs competitively on ARC (MAE$=$0.056) but lacks the uncertainty quantification and domain-level diagnosis that IRT provides. B1-Remove\\&Rescore and B5-Emperor do not improve over raw scores, which confirms that item removal and mitigation strategies are insufficient for calibration.\n\n\\begin{table}[h]\n\\centering\n\\caption{Full baseline comparison on ARC-Challenge (pooled 0.5B+1.5B, $J=8$, S2-only exposure). MAE$\\downarrow$.}\n\\label{tab:full_baselines_arc}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\nMethod & ARC MAE \\\\\n\\midrule\nB0-Raw & 0.059 \\\\\nB1-Remove\\&Rescore & 0.059 \\\\\nB2-Single2PL+$\\gamma$ & 0.064 \\\\\nB3-Vanilla4PL & 0.071 \\\\\nB4-LinearRegression & 0.056 \\\\\nB5-Emperor & 0.059 \\\\\nB6-DCR & --- \\\\\n\\midrule\nContamCal (4PL+$\\gamma$) & \\textbf{0.035} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Baseline comparison on GSM8K (0.5B scale, delta exposure). MAE$\\downarrow$.}\n\\label{tab:full_baselines_gsm8k}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\nMethod & GSM8K MAE \\\\\n\\midrule\nB0-Raw & 0.003 \\\\\nB2-Single2PL+$\\gamma$ & 0.320 \\\\\nB3-Vanilla4PL & 0.012 \\\\\nB4-LinearRegression & \\textbf{0.003} \\\\\nB6-DCR & --- \\\\\n\\midrule\nContamCal (4PL+$\\gamma$) & 0.020 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Parametric Dose-Response Model Comparison}\n\\label{sec:parametric_dr}\n\nWe fit four parametric dose-response models (Constant, Linear, Quadratic, and four-parameter Hill \\citep{hill1910aggregation,ritz2015dose}) to pooled multi-seed MMLU accuracy trajectories for each family. Table~\\ref{tab:aicc_dr} reports AICc and Akaike weights.\n\n\\begin{table}[h]\n\\centering\n\\caption{AICc model selection for dose-response trajectories (pooled multi-seed MMLU). Bold indicates best-fitting model per family; $w$ is the Akaike weight of the best model.}\n\\label{tab:aicc_dr}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\nFamily & Constant & Linear & Quadratic & Hill & Best ($w$) \\\\\n\\midrule\nPhi-4 14.7B & $-$71.42 & $-$72.08 & $-$70.06 & $\\mathbf{-73.14}$ & Hill (0.58) \\\\\nQwen2.5-14B & 49.54 & 23.40 & 21.22 & $\\mathbf{18.28}$ & Hill (0.55) \\\\\nQwen2.5-7B & $-$12.38 & $-$20.53 & $-$14.52 & $\\mathbf{-24.97}$ & Hill (0.77) \\\\\nGemma-2 9B & $\\mathbf{17.35}$ & 18.89 & 20.01 & 18.96 & Constant (0.39) \\\\\nOLMo-2 7B & $\\mathbf{25.82}$ & 26.66 & 27.54 & 26.47 & Constant (0.62) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nParametric model selection with pooled multi-seed data recovers only the most extreme pattern (Collapse, Qwen-14B; Hill $E_{\\max} = -43$pp). Two families classified as Benefit by Algorithm~\\ref{alg:profile-classification} (Gemma-2, OLMo-2) are indistinguishable from Constant under AICc, consistent with their cross-seed CIs crossing zero (Table~\\ref{tab:cross_seed}). Qwen-7B's V-recovery is structurally inaccessible to monotonic Hill/sigmoid models; Quadratic captures the V-shape but is penalized by AICc ($\\Delta$AICc$=$6.4). Phi-4's Immune classification is reclassified as weak Benefit (Hill $E_{\\max} = +2.43$pp, CI [$-$2.01, $+$6.88] crossing zero). These discrepancies reflect insufficient statistical power at $n\\!=\\!3$ seeds rather than contradictions: Algorithm~\\ref{alg:profile-classification} resolves per-seed patterns below the detection threshold of pooled parametric methods, motivating its use for profile construction.\n\n\\section{Exposure Score Item-Level Classification}\n\\label{sec:sij_classification}\n\nUnder controlled injection where ground-truth contamination labels are available, we evaluate item-level classification performance of each detection signal and the RRF fusion (\\S\\ref{sec:stage1}). S1 (embedding similarity) achieves near-perfect discrimination (ROC-AUC 0.93--0.99 across benchmarks and dosage levels), confirming that cosine similarity to the training corpus reliably identifies injected items. RRF fusion achieves ROC-AUC 0.73--0.93, reduced relative to S1 because S2 (Min-K\\%++, AUC $\\approx$ 0.48--0.50) and S4 (Self-Critique, AUC $\\approx$ 0.47--0.51) contribute near-random item-level signal. However, RRF is designed for the realistic setting where ground truth is unavailable: S1 requires an explicit training corpus reference, which practitioners typically lack, while RRF's multi-signal approach provides robustness across detection scenarios where no single signal dominates (\\S\\ref{sec:rrf_ablation}).\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform related-work section.\n\\end{itemize}\n",
      "numLines": 663,
      "startLine": 1,
      "totalLines": 663
    }
  },
  "sourceToolAssistantUUID": "3a6db8e7-0fe9-4f95-8e0f-0600f127575e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-25T09:53:46.478Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HMLGhcXuNCNhB1LJrqdh2S`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ebaf1396-1670-46b1-b0f9-7ee28b86ee09",
  "isSidechain": false,
  "requestId": "req_011CbP5oVDxBqqu7rtErw9ZH",
  "type": "assistant",
  "uuid": "329aaf76-bc0e-4bdb-a5b6-aea8f43d9809",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019aH2GSGRKk5sEvUy4NoF5S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11983,
      "cache_read_input_tokens": 38776,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11983,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 38776,
          "cache_creation_input_tokens": 11983,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11983
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

_source line 41 · 2026-05-25T09:53:46.491Z_

<details><summary>↩ Tool result · `toolu_01HMLGhcXuNCNhB1LJrqdh2S`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review,hyperref]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage{amsmath}
6	\usepackage{amssymb}
7	\usepackage{graphicx}
8	\usepackage{booktabs}
9	\usepackage{multirow}
10	\usepackage{xcolor}
11	\usepackage{subcaption}
12	\usepackage{algorithm}
13	\usepackage{algpseudocode}
14	\usepackage{float}
15	\usepackage{alphalph}
16	\usepackage{tikz}
17	\usetikzlibrary{arrows.meta,positioning,shapes.geometric}
18	\usepackage{flushend}
19	
20	\setlength{\belowcaptionskip}{-8pt}
21	\setlength{\textfloatsep}{8pt plus 2pt minus 2pt}
22	\setlength{\floatsep}{6pt plus 2pt minus 2pt}
23	
24	\title{Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families}
25	
26	\author{Anonymous}
27	
28	\begin{document}
29	\maketitle
30	
31	\begin{abstract}
32	\input{abstract}
33	\end{abstract}
34	
35	\input{introduction}
36	\input{related_work}
37	\input{method}
38	\input{experimental_setup}
39	\input{results}
40	\input{conclusion}
41	
42	\input{limitations}
43	\input{ethics}
44	
45	\bibliography{references}
46	
47	\input{appendix}
48	
49	\end{document}
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "329aaf76-bc0e-4bdb-a5b6-aea8f43d9809",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "7674220d-60f6-42e1-9c73-581afe00df47",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\\usepackage[review,hyperref]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage{algorithm}\n\\usepackage{algpseudocode}\n\\usepackage{float}\n\\usepackage{alphalph}\n\\usepackage{tikz}\n\\usetikzlibrary{arrows.meta,positioning,shapes.geometric}\n\\usepackage{flushend}\n\n\\setlength{\\belowcaptionskip}{-8pt}\n\\setlength{\\textfloatsep}{8pt plus 2pt minus 2pt}\n\\setlength{\\floatsep}{6pt plus 2pt minus 2pt}\n\n\\title{Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\begin{abstract}\n\\input{abstract}\n\\end{abstract}\n\n\\input{introduction}\n\\input{related_work}\n\\input{method}\n\\input{experimental_setup}\n\\input{results}\n\\input{conclusion}\n\n\\input{limitations}\n\\input{ethics}\n\n\\bibliography{references}\n\n\\input{appendix}\n\n\\end{document}\n",
      "numLines": 50,
      "startLine": 1,
      "totalLines": 50
    }
  },
  "sourceToolAssistantUUID": "329aaf76-bc0e-4bdb-a5b6-aea8f43d9809",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 42 · 2026-05-25T09:53:46.496Z_

```json
{
  "parentUuid": "7674220d-60f6-42e1-9c73-581afe00df47",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "4445b3a3-744e-405d-b0ff-c737917054d0",
  "timestamp": "2026-05-25T09:53:46.496Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 43_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：contamcal-irt-calibration Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 39 wa…",
  "leafUuid": "4445b3a3-744e-405d-b0ff-c737917054d0",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 44_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 contamcal-irt-calibration paper audit",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Assistant

_source line 45 · 2026-05-25T09:53:50.280Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the .tex files. Let me also do some targeted searches for AI-style markers and other specific patterns.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4445b3a3-744e-405d-b0ff-c737917054d0",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "e9ad337c-fd49-4d61-83f4-ba9d551f87cd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 46 · 2026-05-25T09:53:51.334Z_

所有源码已读取。现在执行定向扫描以支持审计。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e9ad337c-fd49-4d61-83f4-ba9d551f87cd",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "e5bd0b0d-4f45-4f7c-b491-3b47b408ab71",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 47 · 2026-05-25T09:53:53.480Z_

<details open><summary>🔧 Tool call — Grep · `toolu_016aKXN1ChMZ62keTnMk8thD`</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e5bd0b0d-4f45-4f7c-b491-3b47b408ab71",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "31544fbf-a495-4e0e-9dbc-115721badf1b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 48 · 2026-05-25T09:53:53.504Z_

<details><summary>↩ Tool result · `toolu_016aKXN1ChMZ62keTnMk8thD`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "31544fbf-a495-4e0e-9dbc-115721badf1b",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "b6baaeee-88a0-4179-a1a2-0b855dfc2ae3",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "31544fbf-a495-4e0e-9dbc-115721badf1b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-25T09:53:54.303Z_

<details open><summary>🔧 Tool call — Grep · `toolu_012JZNCrtos26KnES9vsjmus`</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b6baaeee-88a0-4179-a1a2-0b855dfc2ae3",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "a6908df8-65ec-42c4-b014-ec0a63cbcd7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 50 · 2026-05-25T09:53:54.316Z_

<details><summary>↩ Tool result · `toolu_012JZNCrtos26KnES9vsjmus`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a6908df8-65ec-42c4-b014-ec0a63cbcd7f",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "1c831271-bac7-424b-834f-8526ba569c1f",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "a6908df8-65ec-42c4-b014-ec0a63cbcd7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 51 · 2026-05-25T09:53:56.194Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01BW3X8UbBnnKFa5uL3RozTq`</summary>

```json
{
  "pattern": "it is worth noting|notably|importantly|it should be noted|it is important to note",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "-i": true,
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1c831271-bac7-424b-834f-8526ba569c1f",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "50c85ad9-f7d5-46ef-b005-0a4c8268a794",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 52 · 2026-05-25T09:53:56.216Z_

<details><summary>↩ Tool result · `toolu_01BW3X8UbBnnKFa5uL3RozTq`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "50c85ad9-f7d5-46ef-b005-0a4c8268a794",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "9af504ef-59dd-4b6b-8495-edfa9096031f",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "50c85ad9-f7d5-46ef-b005-0a4c8268a794",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 53 · 2026-05-25T09:53:57.615Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Et7Aiu5VZXYviU9ZvtayhM`</summary>

```json
{
  "pattern": "delve|leverage|utilize|facilitate|myriad|plethora",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "-i": true,
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9af504ef-59dd-4b6b-8495-edfa9096031f",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "80df58c8-552e-41b9-ae38-48d0688e95a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 54 · 2026-05-25T09:53:57.642Z_

<details><summary>↩ Tool result · `toolu_01Et7Aiu5VZXYviU9ZvtayhM`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "80df58c8-552e-41b9-ae38-48d0688e95a9",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "5b61cc4b-216b-41ab-8c4c-bc701123a279",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "80df58c8-552e-41b9-ae38-48d0688e95a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 55 · 2026-05-25T09:53:59.482Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01PQPopz8nVJypvxkA1boNRj`</summary>

```json
{
  "pattern": ", (demonstrating|highlighting|showcasing|illustrating|enabling|suggesting|indicating|revealing|confirming|showing) ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5b61cc4b-216b-41ab-8c4c-bc701123a279",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "d00cf9a4-ff5c-4e4d-bddc-19cf30c7b197",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 56 · 2026-05-25T09:53:59.519Z_

<details><summary>↩ Tool result · `toolu_01PQPopz8nVJypvxkA1boNRj`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/abstract.tex:1:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:11:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:13:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:67:Table~\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:112:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:115:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:148:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:151:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:349:\caption{Difference-in-differences (treated vs.\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\S\ref{sec:memorization_test}) is consistent across the full dosage range.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:394:On MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:546:\paragraph{Point estimates.} Under the Linear DGP, $\hat{\gamma}/\gamma_{\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\hat{\gamma}/\gamma_{\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:652:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/experimental_setup.tex:20:\textbf{GSM8K} \citep{cobbe2021gsm8k}: 1,319 open-ended math problems whose free-form generation format avoids multiple-choice artifacts. Gemma-2 is excluded from GSM8K cross-benchmark analysis because MC-format SFT destroys its chain-of-thought (CoT) reasoning: the d000 baseline drops to 17.8\% (vs.\ 73--84\% for other families), indicating CoT collapse rather than a contamination effect.
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex:22:LLaMA-3.1-8B (Meta; d000, d025, d100) is classified Immune on both MMLU ($-$0.69pp) and ARC ($+$0.09pp), despite matching OLMo-2's Benefit baseline (53.5\% vs.\ 53.8\%), indicating that family-level factors beyond baseline ability modulate vulnerability. LLaMA-3.1 also shows the strongest GSM8K transfer ($+$16.4pp; Appendix~\ref{sec:gsm8k_dose_response}): target-benchmark immunity does not imply transfer immunity.
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex:102:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex:104:ContamCal's primary diagnostic value lies in domain-level $\gamma_d$ estimates with credible intervals: Social Sciences $\gamma_d = -0.63$ ($P(\gamma_d\!<\!0) = 99.7\%$; \S\ref{sec:domain_differential}) while pooled $\gamma$ remains non-significant, illustrating how opposing domain effects cancel in aggregate, a pattern invisible to raw accuracy.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d00cf9a4-ff5c-4e4d-bddc-19cf30c7b197",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "fe97b601-1ff0-482f-bf13-7310acd3ccc2",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/abstract.tex:1:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:11:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:13:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:67:Table~\\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:112:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:115:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:148:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:151:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:349:\\caption{Difference-in-differences (treated vs.\\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\\S\\ref{sec:memorization_test}) is consistent across the full dosage range.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:394:On MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:546:\\paragraph{Point estimates.} Under the Linear DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:652:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/experimental_setup.tex:20:\\textbf{GSM8K} \\citep{cobbe2021gsm8k}: 1,319 open-ended math problems whose free-form generation format avoids multiple-choice artifacts. Gemma-2 is excluded from GSM8K cross-benchmark analysis because MC-format SFT destroys its chain-of-thought (CoT) reasoning: the d000 baseline drops to 17.8\\% (vs.\\ 73--84\\% for other families), indicating CoT collapse rather than a contamination effect.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex:22:LLaMA-3.1-8B (Meta; d000, d025, d100) is classified Immune on both MMLU ($-$0.69pp) and ARC ($+$0.09pp), despite matching OLMo-2's Benefit baseline (53.5\\% vs.\\ 53.8\\%), indicating that family-level factors beyond baseline ability modulate vulnerability. LLaMA-3.1 also shows the strongest GSM8K transfer ($+$16.4pp; Appendix~\\ref{sec:gsm8k_dose_response}): target-benchmark immunity does not imply transfer immunity.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex:102:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/results.tex:104:ContamCal's primary diagnostic value lies in domain-level $\\gamma_d$ estimates with credible intervals: Social Sciences $\\gamma_d = -0.63$ ($P(\\gamma_d\\!<\\!0) = 99.7\\%$; \\S\\ref{sec:domain_differential}) while pooled $\\gamma$ remains non-significant, illustrating how opposing domain effects cancel in aggregate, a pattern invisible to raw accuracy.",
    "numLines": 16
  },
  "sourceToolAssistantUUID": "d00cf9a4-ff5c-4e4d-bddc-19cf30c7b197",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 57 · 2026-05-25T09:54:00.459Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01VJEzvmasR8qTB6YQ2GaBeN`</summary>

```json
{
  "pattern": "Furthermore|Moreover|Additionally",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fe97b601-1ff0-482f-bf13-7310acd3ccc2",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "4e7d6c31-ce03-4cb0-9aac-f94a8826d3c9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 58 · 2026-05-25T09:54:00.476Z_

<details><summary>↩ Tool result · `toolu_01VJEzvmasR8qTB6YQ2GaBeN`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:231:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4e7d6c31-ce03-4cb0-9aac-f94a8826d3c9",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "2c51b881-2127-43b7-843a-876fabbd4908",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:231:[Omitted long matching line]",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "4e7d6c31-ce03-4cb0-9aac-f94a8826d3c9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 59 · 2026-05-25T09:54:01.446Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01HgszKwaRxqYzBaM7JfWzjo`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper && cat abstract.tex | wc -w",
  "description": "Count abstract word count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c51b881-2127-43b7-843a-876fabbd4908",
  "isSidechain": false,
  "requestId": "req_011CbP5pCDYDQZJsAXwGrCUt",
  "type": "assistant",
  "uuid": "ab5445c0-d400-47d9-aed3-fe777b36b870",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014FXeiypjZxabLJjwRtFPEC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 73770,
      "cache_read_input_tokens": 11846,
      "output_tokens": 1018,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 73770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1018,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 73770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 73770
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

_source line 60 · 2026-05-25T09:54:01.642Z_

<details><summary>↩ Tool result · `toolu_01HgszKwaRxqYzBaM7JfWzjo`</summary>

```text
192
Shell cwd was reset to /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ab5445c0-d400-47d9-aed3-fe777b36b870",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "f09ca134-267e-474c-ba02-62f0636ff630",
  "toolUseResult": {
    "stdout": "192",
    "stderr": "\nShell cwd was reset to /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "ab5445c0-d400-47d9-aed3-fe777b36b870",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 61 · 2026-05-25T09:54:05.366Z_

<details><summary>Logged reasoning block</summary>

```text
Let me also check some more patterns, like the "-ing" participle phrases at the end of sentences (common AI style), and check for statistics/significance claims.

Let me also count the word count for the limitations section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f09ca134-267e-474c-ba02-62f0636ff630",
  "isSidechain": false,
  "requestId": "req_011CbP5qJy7oYMpZKPdfyJ2E",
  "type": "assistant",
  "uuid": "cf903d8f-2b53-4739-805c-83b065aca67c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014geCoooWjjtuZ4ypFaqd3F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2846,
      "cache_read_input_tokens": 85616,
      "output_tokens": 646,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2846,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 646,
          "cache_read_input_tokens": 85616,
          "cache_creation_input_tokens": 2846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2846
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

_source line 62 · 2026-05-25T09:54:05.945Z_

继续扫描 limitations 长度和其他关键模式。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cf903d8f-2b53-4739-805c-83b065aca67c",
  "isSidechain": false,
  "requestId": "req_011CbP5qJy7oYMpZKPdfyJ2E",
  "type": "assistant",
  "uuid": "ad7616db-a74a-4b49-a69f-980ed0433761",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014geCoooWjjtuZ4ypFaqd3F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2846,
      "cache_read_input_tokens": 85616,
      "output_tokens": 646,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2846,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 646,
          "cache_read_input_tokens": 85616,
          "cache_creation_input_tokens": 2846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2846
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

_source line 63 · 2026-05-25T09:54:06.917Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01DiUivVmGmwvo1bjr5Fi6C8`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper && cat limitations.tex | wc -w",
  "description": "Count limitations word count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ad7616db-a74a-4b49-a69f-980ed0433761",
  "isSidechain": false,
  "requestId": "req_011CbP5qJy7oYMpZKPdfyJ2E",
  "type": "assistant",
  "uuid": "0a9503e0-d093-4563-bec1-59aba43116a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014geCoooWjjtuZ4ypFaqd3F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2846,
      "cache_read_input_tokens": 85616,
      "output_tokens": 646,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2846,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 646,
          "cache_read_input_tokens": 85616,
          "cache_creation_input_tokens": 2846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2846
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

_source line 64 · 2026-05-25T09:54:10.624Z_

<details><summary>↩ Tool result · `toolu_01MpyySYEc8Y6LbPqUSmjLMf`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:11:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "337c1f87-c387-49f4-b386-73d9be19f35f",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "50d86d2d-173a-4721-ad96-b67987519fcb",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex:11:[Omitted long matching line]",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "337c1f87-c387-49f4-b386-73d9be19f35f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 65 · 2026-05-25T09:54:06.994Z_

<details><summary>↩ Tool result · `toolu_01DiUivVmGmwvo1bjr5Fi6C8`</summary>

```text
79
Shell cwd was reset to /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0a9503e0-d093-4563-bec1-59aba43116a9",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "12caae5f-f952-4de2-bdb0-b3640afe17b3",
  "toolUseResult": {
    "stdout": "79",
    "stderr": "\nShell cwd was reset to /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "0a9503e0-d093-4563-bec1-59aba43116a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 66 · 2026-05-25T09:54:07.843Z_

<details open><summary>🔧 Tool call — Grep · `toolu_0146tYPcPCsXRQAwXgKUVhkd`</summary>

```json
{
  "pattern": "significantly|state-of-the-art|SOTA",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "-i": true,
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "12caae5f-f952-4de2-bdb0-b3640afe17b3",
  "isSidechain": false,
  "requestId": "req_011CbP5qJy7oYMpZKPdfyJ2E",
  "type": "assistant",
  "uuid": "724859e6-d48e-4bf3-a164-6a02d59cd54e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014geCoooWjjtuZ4ypFaqd3F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2846,
      "cache_read_input_tokens": 85616,
      "output_tokens": 646,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2846,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 646,
          "cache_read_input_tokens": 85616,
          "cache_creation_input_tokens": 2846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2846
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

_source line 67 · 2026-05-25T09:54:07.864Z_

<details><summary>↩ Tool result · `toolu_0146tYPcPCsXRQAwXgKUVhkd`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "724859e6-d48e-4bf3-a164-6a02d59cd54e",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "e6623603-4606-4544-81f5-bd5eeee854c9",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "724859e6-d48e-4bf3-a164-6a02d59cd54e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 68 · 2026-05-25T09:54:09.276Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01DDQPPsxGgKRuN9mRfN7Vge`</summary>

```json
{
  "pattern": "\\\\section\\*?\\{Limitations\\}|\\\\section\\*?\\{Limitation\\}",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6623603-4606-4544-81f5-bd5eeee854c9",
  "isSidechain": false,
  "requestId": "req_011CbP5qJy7oYMpZKPdfyJ2E",
  "type": "assistant",
  "uuid": "efc81925-bfb2-44fe-9019-a2ed5ed06738",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014geCoooWjjtuZ4ypFaqd3F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2846,
      "cache_read_input_tokens": 85616,
      "output_tokens": 646,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2846,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 646,
          "cache_read_input_tokens": 85616,
          "cache_creation_input_tokens": 2846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2846
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

_source line 69 · 2026-05-25T09:54:09.295Z_

<details><summary>↩ Tool result · `toolu_01DDQPPsxGgKRuN9mRfN7Vge`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex:1:\section*{Limitations}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "efc81925-bfb2-44fe-9019-a2ed5ed06738",
  "isSidechain": false,
  "promptId": "e6418cc2-48b2-4e27-bc1c-735271578fdc",
  "type": "user",
  "uuid": "4be055c0-ca67-484a-bcf7-7f8b73617085",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex:1:\\section*{Limitations}",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "efc81925-bfb2-44fe-9019-a2ed5ed06738",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 70 · 2026-05-25T09:54:10.604Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01MpyySYEc8Y6LbPqUSmjLMf`</summary>

```json
{
  "pattern": "remarkably|revolutionary|groundbreaking|novel|paradigm shift",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper",
  "output_mode": "content",
  "-i": true,
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4be055c0-ca67-484a-bcf7-7f8b73617085",
  "isSidechain": false,
  "requestId": "req_011CbP5qJy7oYMpZKPdfyJ2E",
  "type": "assistant",
  "uuid": "337c1f87-c387-49f4-b386-73d9be19f35f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014geCoooWjjtuZ4ypFaqd3F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2846,
      "cache_read_input_tokens": 85616,
      "output_tokens": 646,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2846,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 646,
          "cache_read_input_tokens": 85616,
          "cache_creation_input_tokens": 2846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2846
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

_source line 71_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：contamcal-irt-calibration Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 39 wa…",
  "leafUuid": "50d86d2d-173a-4721-ad96-b67987519fcb",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 72_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 contamcal-irt-calibration paper audit",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 73 · 2026-05-25T09:54:11.084Z_

```json
{
  "parentUuid": "50d86d2d-173a-4721-ad96-b67987519fcb",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "882d7adf-6471-4d2b-9501-8be2de0c28dc",
  "timestamp": "2026-05-25T09:54:11.084Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 74 · 2026-05-25T09:59:31.704Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me do a thorough audit. Let me also check for "statistically significant" claims and whether they have supporting evidence.

Let me also check for appendix limitations sections (the user rule says only one limitations section allowed in the main text, not in appendix).

Let me also check the abstract word count more carefully - 192 words, the EMNLP limit is 200 words. That's fine.

Now let me systematically go through each audit dimension.

### 1. 叙事一致性 (CRITICAL)

**Abstract's problem:**
- "Benchmark contamination is widely assumed to inflate language model scores, yet its actual effect has never been measured across model families."


- The core issue is that uniform inflation assumptions haven't been empirically validated across different model families.

**Intro's problem:**
- "what is the actual effect of contamination on aggregate scores? The implicit assumption is uniform inflation, but this has never been tested across model families."
- ✅ Matches abstract.

**Intro's contributions:**
1. Dose-response profiles with cross-seed and cross-benchmark validation
2. Domain-level contamination diagnosis via IRT (ContamCal)
3. Diagnostic pipeline requirements and signal failure

**Method actually does:**
- Stage 1: Multi-signal exposure mapping (RRF fusion) ✅ matches contribution 2&3
- Stage 2: Contamination-aug

The method follows through on all three contributions: the multi-signal exposure mapping handles the diagnostic requirements, the IRT-based contamination calibration provides domain-level diagnosis, and the dose-response classification captures the cross-validation aspect. The underlying motivation is that when benchmark items appear in training data, the measured ability scores conflate genuine capability with memorization—exactly the gap the introduction identifies. The experiments systematically validate each piece: dose-response profiles, cross-benchmark transfer, cross-seed stability, item-level memorization effects, diagnostic utility, failure modes, and domain-level analysis.

The conclusion reinforces that controlled SFT injection reveals heterogeneous dose-response patterns rather than uniform inflation, with replication across independent families and no evidence of item-specific memorization effects. The direction of effects generalizes across seeds though the magnitude varies. This aligns with the experimental findings, and the narrative stays consistent with the abstract and introduction's emphasis on spectrum patterns and ContamCal as a diagnostic framework—though I'm noticing the Discussion and Conclusion section is quite brief and might not fully explore the broader implications beyond just restating the results.

Looking at the structure, the conclusion does include interpretation beyond raw numbers: it discusses contamination versus additional training effects and practical implications. The merged Discussion-Conclusion format works for ACL/EMNLP venues. However, there's a potential narrative inconsistency I should flag—the abstract claims ContamCal enables domain-level diagnosis "across model families," but the core IRT calibration analysis only uses the Qwen2.5 family (16 models), while the cross-family validation is limited to dose-response profiling rather than the full diagnostic framework. The dose-response patterns are shown across multiple model families, but the ContamCal diagnostic framework with the domain-level findings about Social Sciences versus STEM effects is only applied to Qwen2.5. The abstract presents these as connected contributions, which could mislead readers into thinking the domain-level analysis spans all families, when it's actually limited to one. , which is indeed done across five model families plus a validation set, so that checks out.

Now looking at the section structure. The abstract covers all the key elements—it identifies the problem that contamination's actual effects haven't been measured, describes the controlled SFT injection method and ContamCal framework, presents the two replicating patterns and benchmark-conditional effects, and emphasizes why model-specific dose-response profiling matters. It's dense at 192 words but within the EMNLP limit.

For the introduction, the background section establishes the context around benchmark scores and contamination.

The problem's importance is woven into the opening, existing mitigation strategies are acknowledged as insufficient, and the approach is clearly stated. The three contributions are listed out. The structure is somewhat compressed with figures and tables appearing early, and there are specific performance numbers throughout, which gives it a results-forward feel. It's a deliberate choice that works for NLP papers, though it reads more like an experiment report than a traditional five-paragraph intro. The condensed approach still covers the necessary ground.

The related work section is well-organized by topic rather than as a flat list, positioning the work effectively against concurrent research.

Now I'm checking how well the contributions align with their supporting evidence throughout the paper. The first contribution on dose-response profiles is backed by the taxonomy, cross-seed analysis, cross-benchmark results, and the key figures and tables. The second contribution on domain-level IRT diagnosis is supported by the IRT model description, calibration results, and domain-level analysis sections.

The third contribution about signal failure and pipeline requirements is grounded in the signal failure analysis and ablation studies in the appendix. I'm also verifying that the item-level memorization test using difference-in-differences fits within the dose-response profiling contribution while also serving as a standalone finding about the mechanism—it's referenced in the introduction as evidence that no item-specific memorization occurs. The title scope checks out since the paper covers five model families plus one validation family, and the abstract accurately describes six models ranging from 7B to 14.7B parameters.

Now I'm checking the strength of each claim against its supporting evidence. The statistical significance for Gemma-2 is backed by bootstrap confidence intervals, the borderline results for OLMo-2 and Falcon3 are appropriately hedged, and the preliminary findings about collapse and V-recovery in Qwen2.5 are correctly framed as pending replication. The claim about no item-specific memorization is supported by Table 7 showing all difference-in-differences p-values above 0.05, and the domain-specific contamination effects—negative for Social Sciences and positive for STEM—are validated through the appendix table and gamma estimates showing 99.7% probability that Social Sciences effects are negative.

The remaining claims about volume-matched controls accounting for 45% of the benefit, Min-K%++ showing directional reversal at 0.5B with a Cohen's d of -1.98, and RRF-based multi-signal fusion being essential are all supported by their respective evidence. One potential issue: the abstract claims that LLaMA-3.1-8B validation "confirms" that family-level factors modulate vulnerability, but a single family can't really confirm a general principle—the results section phrases this more carefully as "indicating" rather than confirming, which is more appropriate for an N=1 validation.

Now looking at the experimental rigor: cross-seed results properly report 95% credible intervals, and the main table includes confidence intervals, though the baseline comparison in Table 2 is just a single run without error bars, which could be worth noting. The baselines are current, pulling from 2024-2025 papers. The ablations cover the key method components—signal ablation, parameterization comparisons, prior sensitivity, and volume control—so those are well-designed.

For reproducibility, the LoRA hyperparameters are specified, training details like learning rate and batch size are documented, and code availability is confirmed with a GitHub link. However, there's a gap: GPU model, actual training time, and compute budget aren't mentioned anywhere in the main text or appendix, despite the appendix noting over 55 checkpoints. The paper does include a limitations section as required. This missing compute information is a meaningful reproducibility concern.

The ethics section file appears empty, but that's acceptable since EMNLP uses a separate responsible NLP checklist in the submission form rather than requiring an ethics section in the PDF itself.

Now checking for notation consistency across the paper, particularly with gamma symbols...

The gamma variants are clearly defined in section 3.2 with subscripts distinguishing pooled, per-benchmark, and per-domain versions. Other key symbols like exposure scores, latent ability, and framework terminology are all used consistently throughout. One minor thing to verify: BCa is defined in the Figure 3 caption but first appears in Table 3 footnotes without that definition, so I should check if it needs to be introduced earlier in the main text. Checking on "MC" — it's used in the method section without being defined upfront. Let me trace back through the introduction and experimental setup to see where it first appears... It looks like "multiple-choice" is mentioned in the experimental setup but "MC" as an abbreviation isn't formally introduced before it's used in the methods.

Now looking at how the sections flow together. The transitions from introduction through related work, methods, experimental setup, results, and discussion all feel natural. The pipeline figure placement in the related work section is a bit unconventional but works structurally.

The discussion and conclusion are quite brief though — just a few paragraphs total. Given the space constraints, there's limited room to explore implications and future directions more deeply.

The limitations section is notably short at 79 words. It does identify key constraints like the model size ceiling at 14.7B parameters and the difference between their LoRA-based approach versus pretraining-stage contamination, but the section cuts off mid-point when discussing the AUGMENT method. The user's explicit instruction that the Limitations section should be brief means I should respect that constraint rather than apply a standard word count. The three limitation points are substantive and avoid superficial language, so this checks out.

Now I'm scanning the paper for AI-style writing patterns—em-dashes, filler words, and overused phrases like "leverage" or "utilize" all come back clean. I'm finding a few participle phrases scattered through the abstract and results sections that are borderline, but they're functioning naturally within their sentences rather than as stylistic padding. That brings the main text count to around 4-5 instances of the "-ing" pattern—worth flagging as a moderate concern. I'm also checking for transition words like Furthermore and Moreover, which appear only once in the appendix, so that's fine. The paragraph lengths look solid throughout, mostly 5+ sentences with no problematic short paragraphs. Now moving into the internal information check—I don't see any experiment IDs, server names, or internal tool references. The paper mentions "55+ checkpoints" without using internal numbering, and there's no language like "in the third round of experiments" that would suggest internal documentation leaking through.

For EMNLP-specific requirements, the abstract comes in at 192 words, well under the 200-word limit. The limitations section is properly placed in the main text only, not duplicated in the appendix. There's just one limitations section as required. The ARR checklist isn't in the PDF itself, which is correct—the appendix does include an "Use of AI Assistants" section though, which is appropriate. The main text appears to be within the 8-page constraint based on the overall page count.

Now I'm noticing that Table 2 shows the baselines actually outperforming ContamCal on raw data, which is a key finding to flag.

Looking at the specific metrics, ContamCal underperforms on MAE compared to B0-Raw and on Kendall's tau versus B5b-Emperor, though the authors frame this honestly by noting that aggregate calibration isn't their primary focus—their strength lies in domain-level diagnosis rather than overall calibration performance.

The Falcon3 cross-seed analysis only uses two seeds while other methods use three, but this limitation is properly disclosed in the tables. Figure 2 showing the pipeline is placed in the related work section for space reasons when it logically belongs in the methods. The conclusion is notably brief.

There's also a reproducibility gap: the paper doesn't specify GPU models, training times, or total compute requirements. And while the appendix appropriately acknowledges Claude usage, I should verify that all appendix sections are actually referenced in the main text.

Going through the appendices, I can confirm that sections A through J are all properly cited from their respective sections in the paper. Let me check if there are any remaining appendices that lack references. Finishing up the appendix cross-references, and now I'm noticing something about the paper's core positioning—it frames ContamCal as a diagnostic framework, but I'm wondering if that framing fully captures what it actually does.

The calibration performance is actually weaker than just using raw accuracy (MAE 0.009 vs 0.006), which the paper acknowledges by saying calibration isn't the primary goal and shifting focus to domain-level diagnosis instead. There's a slight mismatch though: the Method section devotes considerable space to the calibrated score machinery, yet the Results show it doesn't outperform the baseline. The real insight—the domain-level contamination effects—gets less methodological emphasis than the calibration infrastructure that enables it. Though actually, that infrastructure is necessary for deriving those domain effects, and the paper does make the pivot clear in Results, so it works out fine.

The abstract captures the actual value proposition well: domain-level diagnosis with credible intervals showing divergent contamination effects across disciplines.

Now I'm checking whether the specific claims about statistical significance hold up. The Gemma-2 benefit matches the reported CI, and OLMo-2's borderline status is correct since its interval crosses zero. But Falcon3 is flagged as borderline in the abstract while its CI [+3.91, +4.19] actually excludes zero—though with only n=2 samples, that's a thin basis for claiming significance. at Table 3: Falcon3 has n=2, both positive. But the abstract says "borderline for OLMo-2 and Falcon3". Let me check if Falcon3 is actually borderline...

In the abstract: "Benefit (statistically significant for Gemma-2, bootstrap 95% CI [+1.49, +3.14]pp; borderline for OLMo-2 and Falcon3)"

In Table 1: Falcon3 has bootstrap stability 96.1% and is marked ✓ for replication. In Table 3: Falcon3 shows CI [+3.91, +4.19] and Direction = Benefit, Consistency = ✓. So Falcon3 is NOT borderline — it has consistent positive results across both seeds, with CI excluding zero.

The abstract classifies Falcon3 as "borderline" which seems inconsistent with the data. Looking at the results section, I see that "exploratory" in the main text becomes "borderline" in the abstract. The key issue is that with n=2, the bootstrap confidence interval is too small a sample size to be considered statistically significant by the paper's standards, even though the CI excludes zero.

So the mismatch is: the abstract uses "borderline" to describe Falcon3's statistical significance status, but the actual effect sizes are strong and consistent (+3.91, +4.19). The "borderline" label seems to refer to the statistical power issue (n=2) rather than the effect size itself. This is a subtle but important distinction that could mislead readers about the strength of the evidence.

Now I'm checking whether Table 1's taxonomy aligns with the abstract's claims. The abstract identifies Phi-4 and LLaMA-3.1 as "Immune," which checks out—Phi-4 is in Table 1, and LLaMA-3.1 appears in the out-of-sample validation section. For Gemma-2, the abstract claims "statistically significant" benefits, and I'm verifying this against the confidence intervals in Table 1.

I also need to verify the "five of six families" claim about GSM8K transfer effects from Figure 4 and Table 4, checking whether MMLU-targeted contamination actually improves GSM8K across the stated number of model families. Qwen-14B also shows the same pattern—it drops significantly on MMLU but gains substantially on GSM8K, which aligns with the abstract's claim about models harmed on one benchmark but helped on another. Now I'm working through the exact model count for the "five of six" statement, since Gemma-2 appears to be excluded from the main table due to its low baseline, which means I need to clarify whether the original experiment included six models from five families or if the count shifts when accounting for exclusions and validation models. Looking at the figure caption more carefully, the "5 of 6" claim actually includes LLaMA-3.1 as a validation model while excluding Gemma-2 due to the CoT collapse issue. The heatmap itself shows all seven entries, but the count in the abstract is somewhat misleading since it mixes the original six families with the held-out validation model. So the discrepancy is that the abstract claims "five of six families" but the heatmap actually shows five of six models improving — and since Qwen counts as one family with two models, it's really four of five families showing improvement, with Phi-4 being the null case. The wording conflates family-level and model-level counts. models rather than families — Qwen has two separate model sizes that both show improvement, which pushes the count to 5 positive results out of 6 total models tested. models, not families.

The abstract says "five of six families" but should say "five of six models" or "four of five families." This is a critical factual inconsistency.

Actually, wait. Let me re-read the abstract: "MMLU-targeted contamination improves GSM8K in five of six families, even those harmed on MMLU."

Hmm, but there are two Qwen models from the same family. If we're counting "families," then Qwen is one family. But if you count it as 6 entries (2 Qwen + 4 others), then it's models not families. The paper uses "families" inconsistently here.

Actually, maybe the paper treats Qwen-7B and Qwen-14B as different scale points within a family but still counts them individually for this statistic. That would make it models, not families. The abstract should say "five of six models."

This is a claim accuracy issue. Looking at the cross-benchmark transfer section, I see the heatmap shows 6 entries and mentions "families" reversing on GSM8K, but the paper's own intro distinguishes between "six models spanning five independent families," so there's an inconsistency in how it uses these terms throughout. So looking at the actual improvement rates across these five families, I'm seeing four of them show clear gains—Qwen2.5, OLMo-2, Falcon3, and LLaMA-3.1 all demonstrate positive movement, while Phi-4 sits right at the borderline with essentially no improvement. That gives me 4 out of 5 families with meaningful gains, which contradicts the abstract's claim of "five of six families." The discrepancy seems to hinge on how the paper is counting—whether Gemma-2 (which was excluded) still factors into the denominator, or if there's a different grouping I'm missing. There's a real inconsistency here — Gemma-2 shows a positive bar in the figure, but the paper excludes it from Table 4 because of the CoT collapse issue. Counting it as one of the five improvers while simultaneously excluding it from the main table is contradictory, so I should flag that.

Now I'm moving on to compile everything I've found. I also notice the paper combines Discussion and Conclusion into a single section rather than keeping them separate, which is fine for a venue like ACL or EMNLP, but the discussion itself is quite sparse — just a couple of short paragraphs totaling maybe 140 words plus a brief summary. Given how much ground the paper covers — the four dose-response patterns, domain-specific effects, cross-benchmark transfer, and the difference-in-differences results — a more thorough discussion would really strengthen the analysis.

Let me also double-check that the numbers cited in the abstract align with what's actually in the paper.

Verifying abstract claims against the results...

the difference-in-differences analysis confirms no item-specific memorization across all conditions. Now I'm compiling the full audit and checking whether the conclusion accurately reflects the findings—the dose-response patterns do vary across model families, replication status is mixed, the DiD results hold up, and the volume-matched control accounts for roughly 45% of the benefit, all of which the conclusion properly captures.

I'm also verifying the narrative flow between introduction and methods: the intro introduces ContamCal as a framework combining multi-signal exposure mapping with contamination-augmented IRT, and the methods section then breaks this down into three stages, so that connection is solid. The company names (Alibaba, Microsoft, Allen AI, Google, TII) are fine for an anonymized EMNLP review since they identify model sources rather than authors, and the submission is correctly marked as anonymous.

Now I'm catching some critical inconsistencies in the results reporting. The abstract claims "five of six families" show GSM8K transfer gains, but the actual count is problematic—it's either four or five families depending on whether Gemma-2 is included, and the paper explicitly excludes Gemma-2 from the analysis due to CoT collapse while still counting it in the abstract. That's a logical contradiction. Additionally, the abstract describes Falcon3's results as "borderline," but the cross-seed data (n=2, both +3.91pp and +4.19pp) shows consistent positive effects—the issue is the small sample size making it exploratory, not the effect size being borderline. The results section correctly frames this as exploratory, so the abstract overstates the uncertainty. I'm also noticing some awkward -ing participle constructions scattered through the text that could be tightened.

There are also some reproducibility gaps: no GPU model, training time, or total compute hours are specified anywhere. The Discussion and Conclusion sections are quite sparse at around 150 words for a paper of this scope, with no explicit future work section. Table 2 showing the baselines lacks error bars or confidence intervals since it's just a single configuration. And while the abstract doesn't explicitly flag that ContamCal's IRT calibration and domain-level diagnosis are only validated on Qwen2.5, that limitation should be stated upfront. I also notice "MC" is used in the methods without being defined.

The Pipeline figure is oddly placed in the Related Work section rather than Methods, and the Limitations section is quite brief at 79 words across 3 points. Now I'm double-checking the "five of six families" claim from the heatmap more carefully to see if that's actually supported by what the figure shows.

Looking at the figure caption, Gemma-2 does show a positive transfer effect (+1.33pp) but comes with a caveat about being excluded from Table 4 due to a low baseline and CoT collapse. The count breaks down as: Qwen positive, Phi-4 near-zero, OLMo-2 positive, Gemma-2 positive with caveats, Falcon3 positive, and LLaMA-3.1 positive—that's 5 of 6 families improving. The figure itself is internally consistent, but there's a tension between the abstract citing this "five of six" result while the paper notes Gemma-2's exclusion elsewhere.

The real issue is whether a +1.33pp improvement on a 17.8% baseline—especially for a model experiencing CoT collapse—should count toward the headline claim. Including it inflates the family count, though the figure and abstract are technically consistent. This feels more like a scope and precision issue than a factual error, so I'd treat it as a warning rather than something critical.

But now I'm checking the actual claim in the abstract: "five of six families" improves on GSM8K. Let me verify this count against what's actually in the data. If Gemma-2 is excluded from the formal analysis but the abstract still counts it, that's where the discrepancy lies. I need to see what the text actually says in section 5.2 to confirm whether this number holds up. Looking at the appendix text more carefully, it says "All five non-excluded families show positive within-family dose-response transfer (+1 to +16pp)," but Phi-4 actually shows a null result with -0.5pp transfer in the main table, which contradicts this claim about all five families being positive. I'm noticing a critical discrepancy—the main text uses seed s123 for Phi-4 (showing -0.5pp), while the appendix table uses seed s0 (showing +1.14pp). This means the abstract's claim about "five of six" families showing positive transfer only holds for s0; with s123, it's actually four of six. I need to verify whether the abstract's claim about "five of six families" is actually referring to families or models. Looking at the study design, there are five original families with six models total, then LLaMA-3.1 adds a sixth family. So the "six families" in the abstract means the original five families plus LLaMA-3.1, and the claim that MMLU-targeted contamination improves GSM8K in five of these six families is seed-dependent — it holds for one seed but not consistently across seeds. This is a legitimate issue worth flagging as a warning since the claim is true for at least one seed, but the abstract should acknowledge this seed-dependency rather than presenting it as a definitive result. The paper appears to be counting Gemma-2 as positive in that "5 of 6" figure despite excluding it from the formal analysis, which creates an inconsistency worth flagging. Since Phi-4's result is also seed-dependent and Gemma-2 shows a CoT collapse, the claim that five families consistently show positive results is defensible but somewhat misleading. I should note these specific issues in my audit output.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "882d7adf-6471-4d2b-9501-8be2de0c28dc",
  "isSidechain": false,
  "requestId": "req_011CbP5r1KWG4ARMKk6Ut7Ri",
  "type": "assistant",
  "uuid": "b20c5dc8-38ed-4b9a-aac1-4fbeb38018b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Pchwmiw5MyMHoQYWbj92Q9",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1012,
      "cache_read_input_tokens": 88462,
      "output_tokens": 17237,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1012,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 17237,
          "cache_read_input_tokens": 88462,
          "cache_creation_input_tokens": 1012,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1012
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

_source line 75 · 2026-05-25T10:00:16.108Z_

所有数据收集完毕。以下是完整的内容结构审计结果。

```
[CONTENT_AUDIT_START]
- [warning] [叙事一致性] abstract.tex:1 "five of six families" GSM8K 转移的计数依赖于种子选择和 Gemma-2 的包含/排除。Table 4 (main text) 将 Gemma-2 排除且用 seed s123 报告 Phi-4 GSM8K Δ=-0.5pp (null)，此时仅 4/5 family 为正；Appendix Table (gsm8k_dose) 用 seed s0 报告 Phi-4 +1.14pp 且称 "all five non-excluded families show positive"。Abstract 的 "five of six" 需要同时将 Gemma-2 (+1.33pp, CoT collapse baseline) 计为正且使用 s0 seed 下的 Phi-4 数据。建议改为 "four of five non-excluded families" 或明确说明 seed 依赖。
- [warning] [叙事一致性] abstract.tex:1 "borderline for OLMo-2 and Falcon3" 但 results.tex §5.3 用词是 "directionally consistent but exploratory"。Falcon3 两个 seed 均为强正 (+3.91, +4.19pp)，效果量不 borderline，是 n=2 导致的统计确信度不足。"borderline" 暗示效果量边界，应改为 "exploratory" 以匹配 Results 用词。
- [warning] [叙事一致性] abstract.tex:1 ContamCal 的 IRT 校准和 domain-level γ_d 诊断仅在 Qwen2.5 within-family ensemble (J=16) 上验证，但 abstract 写法 "enables domain-level contamination diagnosis" 读起来像通用能力。建议加限定词如 "within-family" 或 "(demonstrated on Qwen2.5)"。
- [warning] [贡献-范围对齐] results.tex:99-106 Table 2 (baselines) 中 ContamCal MAE=0.009 劣于 B0-Raw MAE=0.006，τ=0.731 劣于 B5b τ=0.789。论文诚实承认 "aggregate calibration is not ContamCal's primary goal"，但 Method §3.2 用大量篇幅描述 calibrated score (Eq.3)，形成 method 强调 vs results 弱化的叙事不平衡。建议在 Method 中更早明确 diagnostic value > calibration value 的定位。
- [warning] [实验严谨性] experimental_setup.tex + results.tex 全文未报告 GPU 型号、单次训练时长、总 GPU-hours。EMNLP Reproducibility Checklist 要求披露计算资源。55+ checkpoints 的训练成本对复现至关重要。
- [warning] [实验严谨性] results.tex:106 Table 2 (baselines) 基于单次 300-item 随机子采样，无 error bars 或 bootstrap CI。子采样引入的方差未量化，削弱了方法对比的可信度。
- [warning] [去AI] abstract.tex:1 "-ing 分词短语": "revealing that Social Sciences contamination effects are negative..." 和 "enabling domain-level contamination diagnosis"。
- [warning] [去AI] results.tex:22 "indicating that family-level factors beyond baseline ability modulate vulnerability"
- [warning] [去AI] results.tex:104 "illustrating how opposing domain effects cancel in aggregate, a pattern invisible to raw accuracy"
- [warning] [去AI] experimental_setup.tex:20 "indicating CoT collapse rather than a contamination effect"
- [warning] [章节结构] conclusion.tex 整个 Discussion and Conclusion 仅约 150 words（3 段），对于含 4 种 dose-response pattern、domain-level 效应异质性、cross-benchmark 转移等复杂发现而言过于简略。无显式 future work 讨论。部分 implication 点（如 contamination 检测信号失效对实践的影响）未展开。
- [info] [符号] method.tex:43 "MC-format benchmarks" 首次使用 "MC" 缩写但未展开为 "multiple-choice (MC)"。experimental_setup.tex 使用全称 "multiple-choice" 但未建立缩写映射。
- [info] [章节结构] related_work.tex:3-8 Pipeline 概览图 (Figure 2) 的 LaTeX 代码放在 Related Work 开头，语义上属于 Method。可能是浮动排版优化，但初读者可能困惑。
- [info] [写作规则] limitations.tex 共 79 words，覆盖 3 个 distinct limitations（模型规模限制、SFT vs pretraining、IRT 子采样），内容实质，符合用户规则 "只需要写一小段"。
- [info] [审稿规则] abstract 192 words，符合 EMNLP 2026 ≤200 words 要求。
- [info] [审稿规则] Limitations section 位于正文（\section*{Limitations}），appendix 中无重复 limitations section，符合 "一篇文章只能有一个 limitations section" 要求。
- [info] [去AI] em-dash (—) 0 处，en-dash ( – ) 0 处，filler words 0 处，AI 黑名单词 (delve/leverage/utilize 等) 0 处。去 AI 整体质量良好。
- [info] [叙事一致性] Intro contributions 三条均在正文有对应 section/table 支撑：C1→§5.1+§5.2+§5.3, C2→§5.5+§5.7, C3→§5.6+Appendix D/E。无孤儿章节。
- [info] [叙事一致性] Conclusion 三段总结与 Results 各节结论一致，无遗漏或矛盾。
- [info] [Claim强度] 全文无 "significantly outperforms"、"state-of-the-art"、"revolutionary" 等过强措辞。Collapse/V-recovery 标注 "preliminary pending independent replication"，cross-seed claim 区分 direction (reproducible) vs magnitude (seed-sensitive)，hedging 到位。
- [info] [内部信息] 未检测到内部实验编号、服务器名、内部工具引用或隐含内部流程表述。GitHub URL 使用匿名化命名 (anonymous-nlp-2026-2)。
[CONTENT_AUDIT_END]
```

**审计摘要**：0 critical, 7 warning, 10 info。

主要发现：
1. Abstract 中 "five of six families" GSM8K 转移计数存在种子依赖和排除不一致问题
2. Abstract 对 Falcon3 用 "borderline" 而 Results 用 "exploratory"，术语不一致
3. ContamCal IRT 诊断范围（仅 Qwen2.5）在 abstract 中未充分限定
4. 缺少计算资源披露（GPU 型号、训练时长、总 GPU-hours）
5. 约 5 处 "-ing" 分词短语是主要残余 AI 风格标记
6. Discussion/Conclusion 对论文复杂度而言偏短

叙事一致性整体良好：Intro→Method→Results→Conclusion 主线统一，贡献-范围对齐，claim 强度匹配适当。去 AI 质量优秀（零 em-dash、零 filler words）。

[AUDIT_DONE]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b20c5dc8-38ed-4b9a-aac1-4fbeb38018b3",
  "isSidechain": false,
  "requestId": "req_011CbP5r1KWG4ARMKk6Ut7Ri",
  "type": "assistant",
  "uuid": "84689262-29f6-4f04-bcb9-59e652c18561",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/.claude/sessions/paper_audit_content_2a70d41c",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Pchwmiw5MyMHoQYWbj92Q9",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1012,
      "cache_read_input_tokens": 88462,
      "output_tokens": 17237,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1012,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 17237,
          "cache_read_input_tokens": 88462,
          "cache_creation_input_tokens": 1012,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1012
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

_source line 76_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：contamcal-irt-calibration Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 39 wa…",
  "leafUuid": "84689262-29f6-4f04-bcb9-59e652c18561",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 77_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 contamcal-irt-calibration paper audit",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 78_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：contamcal-irt-calibration Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 39 wa…",
  "leafUuid": "84689262-29f6-4f04-bcb9-59e652c18561",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

### Runtime record

_source line 79_

```json
{
  "type": "ai-title",
  "aiTitle": "EMNLP 2026 contamcal-irt-calibration paper audit",
  "sessionId": "1e2075ff-846f-45a6-9f90-c21d252fe0bd"
}
```

---

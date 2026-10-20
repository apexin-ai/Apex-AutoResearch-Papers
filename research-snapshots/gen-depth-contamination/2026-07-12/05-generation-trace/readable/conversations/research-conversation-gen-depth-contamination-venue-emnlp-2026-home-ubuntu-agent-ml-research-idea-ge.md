# Research conversation: 项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-cont

**Generational Depth Estimation of Recursive Synthetic Text: Measuring the Discrimination Boundary (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 109
- **Recorded user turns:** 1
- **Tool calls:** 33
- **Original source:** `logs/chats/exported-trajectories/account-2/62984386-f345-40e1-a05b-dba4cbd3d2a6.jsonl`
- **Structured JSON:** [`7edf7ca5cf7b1a37439d.json`](../../sessions/7e/7edf7ca5cf7b1a37439d.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-21T06:34:36.986Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-21T06:34:36.986Z",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "content": "项目：gen-depth-contamination\nVenue：emnlp-2026\n论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper\n\nPhase 1 确定性检查结果：\n源码检查: passed=True, 0 critical, 63 warning\n一致性检查: 1 critical, 0 warning\n编译: ✅, 页数: 31\n\n请按照你的角色指令执行内容结构审计。"
}
```

---

### Runtime record

_source line 2 · 2026-05-21T06:34:36.989Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-21T06:34:36.989Z",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

## Round 1

107 recorded events

### User

_source line 3 · 2026-05-21T06:34:37.042Z_

项目：gen-depth-contamination
Venue：emnlp-2026
论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper

Phase 1 确定性检查结果：
源码检查: passed=True, 0 critical, 63 warning
一致性检查: 1 critical, 0 warning
编译: ✅, 页数: 31

请按照你的角色指令执行内容结构审计。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "6d200f89-9750-46a0-a2dc-a7465526aa86",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-21T06:34:37.042Z_

```json
{
  "parentUuid": "6d200f89-9750-46a0-a2dc-a7465526aa86",
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
  "uuid": "d2706434-cc73-4696-8fd6-b85ad6b38221",
  "timestamp": "2026-05-21T06:34:37.042Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-21T06:34:37.042Z_

```json
{
  "parentUuid": "d2706434-cc73-4696-8fd6-b85ad6b38221",
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
  "uuid": "60c7fcd5-d305-4650-9fa7-8e801ff51b0c",
  "timestamp": "2026-05-21T06:34:37.042Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-21T06:34:37.042Z_

```json
{
  "parentUuid": "60c7fcd5-d305-4650-9fa7-8e801ff51b0c",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "4944f6bf-bbcf-4758-970d-6a41661a254e",
  "timestamp": "2026-05-21T06:34:37.042Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
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
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Assistant

_source line 8 · 2026-05-21T06:34:41.502Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to execute a content structure audit on the paper. Let me follow the instructions:

1. Read `skills/global/paper-writing-norms.skill.md` and `skills/global/paper-quality-lessons.skill.md` for audit standards
2. Read all `.tex` files in the paper directory
3. Audit across all dimensions
4. Output structured findings

Let me start by reading the skill files and finding all .tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4944f6bf-bbcf-4758-970d-6a41661a254e",
  "isSidechain": false,
  "requestId": "req_011CbFFPgoghFy8MPDpDthF3",
  "type": "assistant",
  "uuid": "939480ce-b4a3-453e-83ab-997771f95055",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WSroi1ZKt2b39BoXTiUJuE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25955,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25955,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25955,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25955
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-21T06:34:42.493Z_

开始内容结构审计。先加载审计标准和论文源码。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "939480ce-b4a3-453e-83ab-997771f95055",
  "isSidechain": false,
  "requestId": "req_011CbFFPgoghFy8MPDpDthF3",
  "type": "assistant",
  "uuid": "6ba38901-6999-40e6-8858-964eea960f68",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WSroi1ZKt2b39BoXTiUJuE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25955,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25955,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25955,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25955
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-21T06:34:43.046Z_

<details open><summary>🔧 Tool call — Read · `toolu_01A8WzrUn474DUgUyDqBbk7i`</summary>

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
  "parentUuid": "6ba38901-6999-40e6-8858-964eea960f68",
  "isSidechain": false,
  "requestId": "req_011CbFFPgoghFy8MPDpDthF3",
  "type": "assistant",
  "uuid": "aede854c-b8ae-47a7-a003-e96e4c1b500d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WSroi1ZKt2b39BoXTiUJuE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25955,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25955,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25955,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25955
          },
          "type": "message"
        }
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

_source line 11 · 2026-05-21T06:34:44.010Z_

<details><summary>↩ Tool result · `toolu_01LNgjFSnP82PFs5895DpxY5`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_alpha_sweep.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_pairwise_significance.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_crossscorer.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_domain_model_kstar.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_domain_model_kstar_full.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_filtering_main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c3.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/conclusion.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6d2e5a95-a2e0-4245-959c-7393b701d7ba",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "c2e98af1-f994-492c-bb0d-7766d51eb9a1",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_alpha_sweep.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_pairwise_significance.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_crossscorer.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_domain_model_kstar.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_domain_model_kstar_full.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_filtering_main.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c3.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/conclusion.tex"
    ],
    "durationMs": 14,
    "numFiles": 16,
    "truncated": false
  },
  "sourceToolAssistantUUID": "6d2e5a95-a2e0-4245-959c-7393b701d7ba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-21T06:34:43.077Z_

<details><summary>↩ Tool result · `toolu_01A8WzrUn474DUgUyDqBbk7i`</summary>

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
  "parentUuid": "aede854c-b8ae-47a7-a003-e96e4c1b500d",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "bcee2740-8d2f-4501-ab1c-6ee520016ee1",
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
  "sourceToolAssistantUUID": "aede854c-b8ae-47a7-a003-e96e4c1b500d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 13 · 2026-05-21T06:34:43.549Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MvVvUpH1eTp1EUHbAALujY`</summary>

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
  "parentUuid": "bcee2740-8d2f-4501-ab1c-6ee520016ee1",
  "isSidechain": false,
  "requestId": "req_011CbFFPgoghFy8MPDpDthF3",
  "type": "assistant",
  "uuid": "09c55d69-d974-4824-8f9c-b28148e68c6c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WSroi1ZKt2b39BoXTiUJuE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25955,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25955,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25955,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25955
          },
          "type": "message"
        }
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

_source line 14 · 2026-05-21T06:34:43.557Z_

<details><summary>↩ Tool result · `toolu_01MvVvUpH1eTp1EUHbAALujY`</summary>

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
  "parentUuid": "09c55d69-d974-4824-8f9c-b28148e68c6c",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "2c191752-6a45-48e5-a86a-63e7c1709db9",
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
  "sourceToolAssistantUUID": "09c55d69-d974-4824-8f9c-b28148e68c6c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 15 · 2026-05-21T06:34:43.991Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01LNgjFSnP82PFs5895DpxY5`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c191752-6a45-48e5-a86a-63e7c1709db9",
  "isSidechain": false,
  "requestId": "req_011CbFFPgoghFy8MPDpDthF3",
  "type": "assistant",
  "uuid": "6d2e5a95-a2e0-4245-959c-7393b701d7ba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WSroi1ZKt2b39BoXTiUJuE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25955,
      "cache_read_input_tokens": 11846,
      "output_tokens": 362,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25955,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 362,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25955,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25955
          },
          "type": "message"
        }
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
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "c2e98af1-f994-492c-bb0d-7766d51eb9a1",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Assistant

_source line 18 · 2026-05-21T06:34:46.879Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read all the .tex files. Let me read them in parallel batches. I'll start with the main files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c2e98af1-f994-492c-bb0d-7766d51eb9a1",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "4d5e11c9-dd2a-45c3-8d3f-57ebe3c63158",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 19 · 2026-05-21T06:34:46.879Z_

读取所有 .tex 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4d5e11c9-dd2a-45c3-8d3f-57ebe3c63158",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "460f6ade-f4e8-49d3-ab90-99448e9fd220",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 20 · 2026-05-21T06:34:47.908Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HSmcoJXuQq8WkqLvQirV1h`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "460f6ade-f4e8-49d3-ab90-99448e9fd220",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "dd87eb53-d0f6-43f9-9cc3-7b687966ebfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 21 · 2026-05-21T06:34:47.913Z_

<details><summary>↩ Tool result · `toolu_01HSmcoJXuQq8WkqLvQirV1h`</summary>

```text
1	% EMNLP 2026 Main - ARR May 2026
2	% Generational Depth Contamination
3	\documentclass[11pt]{article}
4	\usepackage[review]{acl}
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{graphicx}
11	\usepackage{amsmath}
12	\usepackage{amssymb}
13	\usepackage{booktabs}
14	\usepackage{multirow}
15	\usepackage{enumitem}
16	\usepackage{subcaption}
17	\usepackage{pifont}
18	\newcommand{\cmark}{\ding{51}}
19	\newcommand{\xmark}{\ding{55}}
20	\usepackage{placeins}
21	
22	\newcommand{\Kstar}{{K^*}}
23	\newcommand{\Kempirical}{{K^*}}
24	\newcommand{\Ktheory}{{K^*_{\text{theory}}}}
25	\newcommand{\auc}{\text{AUC}}
26	\newcommand{\jsd}{\text{JSD}}
27	\newcommand{\tpm}{\ensuremath{\,\pm\,}}
28	
29	\title{Generational Depth Estimation of Recursive Synthetic Text:\\Measuring the Discrimination Boundary}
30	
31	\author{Anonymous}
32	
33	\begin{document}
34	\maketitle
35	
36	% === Abstract ===
37	\begin{abstract}
38	Web-scale corpora are increasingly contaminated by recursive synthetic content, yet no method estimates a document's generational depth.
39	We measure the discrimination boundary $\Kempirical$, defined as the maximum depth at which adjacent generations remain statistically distinguishable, under prompt-chain generation using largely generator-invariant statistical features and an ordinal classifier.
40	The $\theta$-invariant domain ordering arXiv ($\Kempirical{=}3$) $>$ C4 ($\Kempirical{=}2$) $=$ Code ($\Kempirical{=}2$) $>$ Wikipedia ($\Kempirical{=}1$) holds across six architecture families ($\leq$14B); within this hierarchy, $\Kempirical{=}2$ at $\theta{=}0.60$ for web text emerges as the dominant mode (four of six families; changepoint-confirmed).
41	The domain ordering is feature-set invariant (preserved under both 15D statistics and DeBERTa fine-tuning), while absolute $\Kempirical$ values are feature-dependent: DeBERTa matches the 15D bound on C4 and Code but extends $\Kempirical$ to 3 on Wikipedia and 4 on arXiv, placing 15D measurements as conservative lower bounds.
42	Multi-source pooling preserves domain-calibrated $\Kempirical$ across all four domains with negligible generator-identity signal; features transfer across generators (80--92\% aggregate accuracy, driven by high 0v1 separability), but boundary-level $\Kempirical$ assignments fail under cross-model transfer (4/6 off-diagonal 7B pairs fall below $\theta$).
43	As a consistency check, $\Kempirical{=}2$ correctly predicts that binary filtering outperforms graduated alternatives for web text.
44	\end{abstract}
45	
46	% === Section 1: Introduction ===
47	\input{introduction}
48	
49	% === Section 2: Related Work ===
50	\input{related_work}
51	
52	% === Section 3: Method ===
53	\input{method}
54	
55	% === Section 4: Experiments ===
56	\input{experiments_c1}
57	
58	% === Section 5: K*-Aware Data Filtering ===
59	\input{experiments_c3}
60	
61	% === Section 6: Discussion ===
62	\input{discussion}
63	
64	% === Section 7: Conclusion ===
65	\input{conclusion}
66	
67	% === Limitations (ACL required, unnumbered) ===
68	\section*{Limitations}
69	
70	All experiments are conducted at $\leq$14B scale (6 architecture families, 10 configurations) with English text across four domains and four decoding strategies; whether $\Kempirical{=}2$ holds at 70B+ scales remains unverified.
71	Main results use prompt-chain only, isolating text-intrinsic degradation; retrain-chain yields $\Kempirical{=}7$ (Appendix~\ref{sec:extended_limitations}), and mixed-chain scenarios are not addressed.
72	Cross-model transfer retains 80--92\% aggregate accuracy but boundary-level $\Kempirical$ assignments remain fragile (4/6 off-diagonal 7B pairs fall below $\theta$; Section~\ref{sec:transfer}).
73	
74	The 15D features yield a feature-set-specific lower bound; DeBERTa extends $\Kempirical$ by $+1$--$2$ on structured domains, suggesting headroom remains.
75	$\Kempirical$ is $\theta$-dependent (ranges from 2--3 at $\theta{=}0.55$ to 1 at $\theta{=}0.70$), though a $\theta$-free changepoint analysis agrees within $\pm 1$ for 35/37 configurations.
76	The filtering evaluation validates on two architectures with small effect sizes (max $+$1.92\,pp), demonstrating strategy ordering rather than large absolute gains.
77	Extended limitations appear in Appendix~\ref{sec:extended_limitations}.
78	
79	% === Ethics Statement (ACL required, unnumbered) ===
80	\section*{Ethics Statement}
81	
82	Generational depth estimation is intended for data curation and corpus auditing, positive-sum applications that improve training data quality.
83	Our experiments use publicly available corpora (C4, Wikipedia, arXiv abstracts) and do not involve personally identifiable information.
84	A potential dual-use concern is that depth estimation techniques could inform adversarial strategies to evade detection (e.g., by calibrating rewriting to mimic earlier-generation statistics); we note that this risk is shared by all detection research and that the binary detection boundary ($\auc \geq 0.96$ at 0v1) remains robust.
85	Code and generated corpora will be released upon acceptance to enable reproducibility.
86	
87	\bibliography{references}
88	
89	\input{appendix}
90	\input{appendix_extended}
91	
92	\end{document}
93	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dd87eb53-d0f6-43f9-9cc3-7b687966ebfd",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "01e72a8b-2f6f-46c0-bc30-2df6ca5d6c28",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex",
      "content": "% EMNLP 2026 Main - ARR May 2026\n% Generational Depth Contamination\n\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{graphicx}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{booktabs}\n\\usepackage{multirow}\n\\usepackage{enumitem}\n\\usepackage{subcaption}\n\\usepackage{pifont}\n\\newcommand{\\cmark}{\\ding{51}}\n\\newcommand{\\xmark}{\\ding{55}}\n\\usepackage{placeins}\n\n\\newcommand{\\Kstar}{{K^*}}\n\\newcommand{\\Kempirical}{{K^*}}\n\\newcommand{\\Ktheory}{{K^*_{\\text{theory}}}}\n\\newcommand{\\auc}{\\text{AUC}}\n\\newcommand{\\jsd}{\\text{JSD}}\n\\newcommand{\\tpm}{\\ensuremath{\\,\\pm\\,}}\n\n\\title{Generational Depth Estimation of Recursive Synthetic Text:\\\\Measuring the Discrimination Boundary}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n% === Abstract ===\n\\begin{abstract}\nWeb-scale corpora are increasingly contaminated by recursive synthetic content, yet no method estimates a document's generational depth.\nWe measure the discrimination boundary $\\Kempirical$, defined as the maximum depth at which adjacent generations remain statistically distinguishable, under prompt-chain generation using largely generator-invariant statistical features and an ordinal classifier.\nThe $\\theta$-invariant domain ordering arXiv ($\\Kempirical{=}3$) $>$ C4 ($\\Kempirical{=}2$) $=$ Code ($\\Kempirical{=}2$) $>$ Wikipedia ($\\Kempirical{=}1$) holds across six architecture families ($\\leq$14B); within this hierarchy, $\\Kempirical{=}2$ at $\\theta{=}0.60$ for web text emerges as the dominant mode (four of six families; changepoint-confirmed).\nThe domain ordering is feature-set invariant (preserved under both 15D statistics and DeBERTa fine-tuning), while absolute $\\Kempirical$ values are feature-dependent: DeBERTa matches the 15D bound on C4 and Code but extends $\\Kempirical$ to 3 on Wikipedia and 4 on arXiv, placing 15D measurements as conservative lower bounds.\nMulti-source pooling preserves domain-calibrated $\\Kempirical$ across all four domains with negligible generator-identity signal; features transfer across generators (80--92\\% aggregate accuracy, driven by high 0v1 separability), but boundary-level $\\Kempirical$ assignments fail under cross-model transfer (4/6 off-diagonal 7B pairs fall below $\\theta$).\nAs a consistency check, $\\Kempirical{=}2$ correctly predicts that binary filtering outperforms graduated alternatives for web text.\n\\end{abstract}\n\n% === Section 1: Introduction ===\n\\input{introduction}\n\n% === Section 2: Related Work ===\n\\input{related_work}\n\n% === Section 3: Method ===\n\\input{method}\n\n% === Section 4: Experiments ===\n\\input{experiments_c1}\n\n% === Section 5: K*-Aware Data Filtering ===\n\\input{experiments_c3}\n\n% === Section 6: Discussion ===\n\\input{discussion}\n\n% === Section 7: Conclusion ===\n\\input{conclusion}\n\n% === Limitations (ACL required, unnumbered) ===\n\\section*{Limitations}\n\nAll experiments are conducted at $\\leq$14B scale (6 architecture families, 10 configurations) with English text across four domains and four decoding strategies; whether $\\Kempirical{=}2$ holds at 70B+ scales remains unverified.\nMain results use prompt-chain only, isolating text-intrinsic degradation; retrain-chain yields $\\Kempirical{=}7$ (Appendix~\\ref{sec:extended_limitations}), and mixed-chain scenarios are not addressed.\nCross-model transfer retains 80--92\\% aggregate accuracy but boundary-level $\\Kempirical$ assignments remain fragile (4/6 off-diagonal 7B pairs fall below $\\theta$; Section~\\ref{sec:transfer}).\n\nThe 15D features yield a feature-set-specific lower bound; DeBERTa extends $\\Kempirical$ by $+1$--$2$ on structured domains, suggesting headroom remains.\n$\\Kempirical$ is $\\theta$-dependent (ranges from 2--3 at $\\theta{=}0.55$ to 1 at $\\theta{=}0.70$), though a $\\theta$-free changepoint analysis agrees within $\\pm 1$ for 35/37 configurations.\nThe filtering evaluation validates on two architectures with small effect sizes (max $+$1.92\\,pp), demonstrating strategy ordering rather than large absolute gains.\nExtended limitations appear in Appendix~\\ref{sec:extended_limitations}.\n\n% === Ethics Statement (ACL required, unnumbered) ===\n\\section*{Ethics Statement}\n\nGenerational depth estimation is intended for data curation and corpus auditing, positive-sum applications that improve training data quality.\nOur experiments use publicly available corpora (C4, Wikipedia, arXiv abstracts) and do not involve personally identifiable information.\nA potential dual-use concern is that depth estimation techniques could inform adversarial strategies to evade detection (e.g., by calibrating rewriting to mimic earlier-generation statistics); we note that this risk is shared by all detection research and that the binary detection boundary ($\\auc \\geq 0.96$ at 0v1) remains robust.\nCode and generated corpora will be released upon acceptance to enable reproducibility.\n\n\\bibliography{references}\n\n\\input{appendix}\n\\input{appendix_extended}\n\n\\end{document}\n",
      "numLines": 93,
      "startLine": 1,
      "totalLines": 93
    }
  },
  "sourceToolAssistantUUID": "dd87eb53-d0f6-43f9-9cc3-7b687966ebfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-21T06:34:48.385Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Kwo5TzCxMCQQ9Ta6n1ovAr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "01e72a8b-2f6f-46c0-bc30-2df6ca5d6c28",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "6d19c28b-64ae-4338-8cd6-a884adaa09d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-21T06:34:48.390Z_

<details><summary>↩ Tool result · `toolu_01Kwo5TzCxMCQQ9Ta6n1ovAr`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Web-scale text corpora are increasingly contaminated by synthetic content that has itself been generated from earlier synthetic content~\cite{sun2025aigt, spennemann2025quantifying}.
5	When synthetic text is recursively fed back, multi-generational content degrades with each iteration~\cite{shumailov2024collapse, dohmatob2024model} through two distinct mechanisms: \emph{retrain-chains} accumulate degradation in model weights through iterative self-training, while \emph{prompt-chains} degrade text statistics through recursive generation by a fixed model.
6	We study prompt-chains, which isolate text-intrinsic information loss and model the dominant web contamination pathway, where synthetic text is produced by one-shot LLM generation rather than iterative retraining.
7	Retrain-chain experiments place the discrimination boundary higher ($\Kempirical{=}7$; Section~\ref{sec:discussion}), framing prompt-chain $\Kempirical{=}2$ as the curation floor within the $[2,7]$ range.
8	For practitioners curating web corpora, the key question is not whether degradation occurs, but at what generational depth it ceases to be detectable.
9	Yet the dominant paradigm treats all machine-generated text identically and ignores the generational depth dimension.
10	
11	\begin{figure*}[t]
12	\centering
13	\includegraphics[width=\textwidth]{figures/pipeline.pdf}
14	\caption{Generational depth estimation pipeline. Seed documents are recursively passed through a generation operator $G_\delta$ to produce a depth chain. Statistical features are fed to the OBD-LightGBM classifier for depth prediction.}
15	\label{fig:pipeline}
16	\end{figure*}
17	
18	This gap cuts across multiple communities: binary detectors~\cite{basani2026diveye, zhang2024minkpp} produce no depth estimate (Section~\ref{sec:binary_confidence}), membership inference~\cite{zawalski2026codec} addresses a different question, and data selection methods~\cite{xie2023dsir, tirumala2023d4, drayson2025} ignore recursive depth.
19	No existing method provides a per-text operational estimate of generational depth backed by statistical guarantees.
20	
21	For data curation, the saturation point determines filtering granularity: if discrimination collapses at depth~2, binary filtering becomes the principled choice; existing model collapse analyses are population-level and do not localize this boundary per text.
22	
23	The Data Processing Inequality implies monotonic cumulative information loss across generations; together with Markov chain convergence (adjacent transitions $Y_{k-1} \to Y_k$ become increasingly similar as the chain approaches stationarity), this motivates a finite discrimination boundary $\Kstar$, whose actual value must be determined empirically.
24	We deliberately employ simple, interpretable features to establish a conservative lower bound on the discrimination boundary; DeBERTa fine-tuning (Section~\ref{sec:neural_probe}) confirms this design by pushing $\Kempirical$ higher on structured domains while matching the 15D bound on web text.
25	We present an empirical characterization study that formalizes $\Kempirical$ (the maximum depth at which a classifier reliably distinguishes adjacent generations) and measures it under prompt-chain generation using 15 statistical features computed via a fixed reference scorer (Section~\ref{sec:features}) and an Ordinal Binary Decomposition (OBD) LightGBM classifier.
26	We operationalize $\Kempirical$ as the deepest $k \geq 1$ where the pairwise $\auc_{k-1,k}$ exceeds $\theta = 0.60$ (Section~\ref{sec:formulation}).
27	
28	Our contributions:
29	\begin{enumerate}[label=(\alph*),nosep]
30	  \item \textbf{First empirical measurement of $\Kempirical$} across 10 model configurations (6 architecture families, 1B--14B), 4 source domains (3 text + 1 code), and 4 decoding strategies at $\theta{=}0.60$: four of six families (7/9 continuation-mode configurations) yield $\Kempirical{=}2$ at $\theta{=}0.60$ on C4 ($p \leq 10^{-4}$; changepoint-confirmed; margin stratification in Section~\ref{sec:kstar_boundary}); multi-source pooling preserves domain-calibrated $\Kempirical$ across all four domains ($+0.010$ mean $\auc$ for generator identity across four domains).
31	  Zero-shot frontier LLMs likewise collapse beyond $\Kempirical$: per-depth recall at depths $\geq 2$ ranges from 8--38\% (vs.\ 20\% chance), indicating error redistribution rather than genuine depth recovery (Section~\ref{sec:why_kstar}).
32	  \item \textbf{Feature-set-invariant domain ordering}: arXiv ($\Kempirical{=}3$) $>$ C4 ($\Kempirical{=}2$) $=$ Code ($\Kempirical{=}2$) $>$ Wikipedia ($\Kempirical{=}1$) holds across tested configurations under both 15D statistics and DeBERTa fine-tuning; absolute $\Kempirical$ values are feature-dependent (15D provides a conservative lower bound), but the ordering is robust (Section~\ref{sec:cross_domain}).
33	  \item \textbf{Transfer and consistency check}: largely generator-invariant features within continuation mode enable 80--92\% accuracy retention among tested configurations ($\rho > 0.90$; Section~\ref{sec:transfer}), though boundary-level $\Kempirical$ assignments are fragile under cross-model transfer (4/6 off-diagonal 7B pairs fall below $\theta$); as a consistency check, domain-appropriate $\Kempirical$ correctly predicts binary ${>}$ graduated filtering for web text (Section~\ref{sec:filtering}).
34	\end{enumerate}
35	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6d19c28b-64ae-4338-8cd6-a884adaa09d4",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "30fc5f82-b052-4125-adde-3dfb2d7fdf00",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nWeb-scale text corpora are increasingly contaminated by synthetic content that has itself been generated from earlier synthetic content~\\cite{sun2025aigt, spennemann2025quantifying}.\nWhen synthetic text is recursively fed back, multi-generational content degrades with each iteration~\\cite{shumailov2024collapse, dohmatob2024model} through two distinct mechanisms: \\emph{retrain-chains} accumulate degradation in model weights through iterative self-training, while \\emph{prompt-chains} degrade text statistics through recursive generation by a fixed model.\nWe study prompt-chains, which isolate text-intrinsic information loss and model the dominant web contamination pathway, where synthetic text is produced by one-shot LLM generation rather than iterative retraining.\nRetrain-chain experiments place the discrimination boundary higher ($\\Kempirical{=}7$; Section~\\ref{sec:discussion}), framing prompt-chain $\\Kempirical{=}2$ as the curation floor within the $[2,7]$ range.\nFor practitioners curating web corpora, the key question is not whether degradation occurs, but at what generational depth it ceases to be detectable.\nYet the dominant paradigm treats all machine-generated text identically and ignores the generational depth dimension.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/pipeline.pdf}\n\\caption{Generational depth estimation pipeline. Seed documents are recursively passed through a generation operator $G_\\delta$ to produce a depth chain. Statistical features are fed to the OBD-LightGBM classifier for depth prediction.}\n\\label{fig:pipeline}\n\\end{figure*}\n\nThis gap cuts across multiple communities: binary detectors~\\cite{basani2026diveye, zhang2024minkpp} produce no depth estimate (Section~\\ref{sec:binary_confidence}), membership inference~\\cite{zawalski2026codec} addresses a different question, and data selection methods~\\cite{xie2023dsir, tirumala2023d4, drayson2025} ignore recursive depth.\nNo existing method provides a per-text operational estimate of generational depth backed by statistical guarantees.\n\nFor data curation, the saturation point determines filtering granularity: if discrimination collapses at depth~2, binary filtering becomes the principled choice; existing model collapse analyses are population-level and do not localize this boundary per text.\n\nThe Data Processing Inequality implies monotonic cumulative information loss across generations; together with Markov chain convergence (adjacent transitions $Y_{k-1} \\to Y_k$ become increasingly similar as the chain approaches stationarity), this motivates a finite discrimination boundary $\\Kstar$, whose actual value must be determined empirically.\nWe deliberately employ simple, interpretable features to establish a conservative lower bound on the discrimination boundary; DeBERTa fine-tuning (Section~\\ref{sec:neural_probe}) confirms this design by pushing $\\Kempirical$ higher on structured domains while matching the 15D bound on web text.\nWe present an empirical characterization study that formalizes $\\Kempirical$ (the maximum depth at which a classifier reliably distinguishes adjacent generations) and measures it under prompt-chain generation using 15 statistical features computed via a fixed reference scorer (Section~\\ref{sec:features}) and an Ordinal Binary Decomposition (OBD) LightGBM classifier.\nWe operationalize $\\Kempirical$ as the deepest $k \\geq 1$ where the pairwise $\\auc_{k-1,k}$ exceeds $\\theta = 0.60$ (Section~\\ref{sec:formulation}).\n\nOur contributions:\n\\begin{enumerate}[label=(\\alph*),nosep]\n  \\item \\textbf{First empirical measurement of $\\Kempirical$} across 10 model configurations (6 architecture families, 1B--14B), 4 source domains (3 text + 1 code), and 4 decoding strategies at $\\theta{=}0.60$: four of six families (7/9 continuation-mode configurations) yield $\\Kempirical{=}2$ at $\\theta{=}0.60$ on C4 ($p \\leq 10^{-4}$; changepoint-confirmed; margin stratification in Section~\\ref{sec:kstar_boundary}); multi-source pooling preserves domain-calibrated $\\Kempirical$ across all four domains ($+0.010$ mean $\\auc$ for generator identity across four domains).\n  Zero-shot frontier LLMs likewise collapse beyond $\\Kempirical$: per-depth recall at depths $\\geq 2$ ranges from 8--38\\% (vs.\\ 20\\% chance), indicating error redistribution rather than genuine depth recovery (Section~\\ref{sec:why_kstar}).\n  \\item \\textbf{Feature-set-invariant domain ordering}: arXiv ($\\Kempirical{=}3$) $>$ C4 ($\\Kempirical{=}2$) $=$ Code ($\\Kempirical{=}2$) $>$ Wikipedia ($\\Kempirical{=}1$) holds across tested configurations under both 15D statistics and DeBERTa fine-tuning; absolute $\\Kempirical$ values are feature-dependent (15D provides a conservative lower bound), but the ordering is robust (Section~\\ref{sec:cross_domain}).\n  \\item \\textbf{Transfer and consistency check}: largely generator-invariant features within continuation mode enable 80--92\\% accuracy retention among tested configurations ($\\rho > 0.90$; Section~\\ref{sec:transfer}), though boundary-level $\\Kempirical$ assignments are fragile under cross-model transfer (4/6 off-diagonal 7B pairs fall below $\\theta$); as a consistency check, domain-appropriate $\\Kempirical$ correctly predicts binary ${>}$ graduated filtering for web text (Section~\\ref{sec:filtering}).\n\\end{enumerate}\n",
      "numLines": 35,
      "startLine": 1,
      "totalLines": 35
    }
  },
  "sourceToolAssistantUUID": "6d19c28b-64ae-4338-8cd6-a884adaa09d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-21T06:34:48.853Z_

<details open><summary>🔧 Tool call — Read · `toolu_011Sn895DUZD1eKPiGvMXPVk`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "30fc5f82-b052-4125-adde-3dfb2d7fdf00",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "c03a48f0-ae62-497e-b52a-32efc555e9d6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 25 · 2026-05-21T06:34:48.858Z_

<details><summary>↩ Tool result · `toolu_011Sn895DUZD1eKPiGvMXPVk`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Formulation}
5	\label{sec:formulation}
6	
7	A generation operator $G_\delta$ (LLM + decoding strategy $\delta$) produces successive generations $X \to Y_1 \to \cdots \to Y_K$, where $Y_k = G_\delta(Y_{k-1})$ and $Y_0 \triangleq X$ (Figure~\ref{fig:pipeline}).
8	This sequence forms a Markov chain.
9	By the Data Processing Inequality, $I(X; Y_1) \geq I(X; Y_2) \geq \cdots \geq 0$: the original signal degrades monotonically.
10	Together with Markov chain convergence, this implies a finite $\Ktheory$ beyond which adjacent generations become indistinguishable; DPI motivates finite $\Ktheory$ but does not formally guarantee or bound it.
11	Specifically, DPI constrains the cumulative divergence from the seed text; the adjacent-pair convergence that determines $\Kempirical$ follows from the chain's approach to its stationary distribution~\cite{levin2017markov}, where successive transition distributions become indistinguishable.
12	The actual saturation depth must therefore be measured empirically.
13	
14	We define the operational lower bound $K^*_{\text{empirical}}$ (hereafter $\Kempirical$), where $S$ denotes the feature set (specified in Section~\ref{sec:features}):
15	\begin{equation}
16	  \Kempirical = \max\!\bigl\{k \!\geq\! 1 : \mathrm{CI}_{\mathrm{low}}(\auc_{j\text{-}1,j}) > \theta,\ \forall j \!\leq\! k\bigr\},
17	  \label{eq:kstar}
18	\end{equation}
19	where $\mathrm{CI}_{\mathrm{low}}(\auc_{k-1,k})$ is the lower bound of a 95\% bootstrap confidence interval (1{,}000 resamples\footnote{We use 1{,}000 resamples as the default for computational efficiency; arXiv cross-scorer CIs (Table~\ref{tab:arxiv_crossscorer_ci}) use 10{,}000 to achieve tighter bounds at marginal boundaries where sub-pp differences determine the $\Kempirical{=}2$ vs.\ $\Kempirical{=}3$ verdict.}) over the pairwise AUC (Area Under the ROC Curve) between depths $k{-}1$ and $k$, and $\theta = 0.60$ is a post-hoc operational threshold (motivated below).
20	This criterion ensures that $\Kempirical$ reflects statistically robust discriminability; the $\forall j \leq k$ constraint is naturally satisfied because $\auc_{k,k+1}$ decreases monotonically above $\theta$ across all tested configurations (Table~\ref{tab:kstar_ci}).
21	While non-monotonic $\auc_{k,k+1}$ is theoretically possible if intermediate generations traverse a high-entropy transient region, we observe strict monotonicity above $\theta$ across all 37 configurations (Table~\ref{tab:kstar_ci_extended}).
22	$\Kempirical$ is jointly conditioned on the feature set and $\theta$; the domain ordering is stable across $\theta \in [0.575, 0.65]$ (Section~\ref{sec:kstar_boundary}). We verify that non-boundary CI upper bounds fall below $\theta$.
23	
24	\paragraph{Threshold choice.}
25	We set $\theta{=}0.60$ at the empirical AUC discontinuity (Figure~\ref{fig:kstar_theta}): 1v2 values cluster at $0.61$--$0.70$ while 2v3 values cluster at $0.55$--$0.59$, creating a ${\sim}$5--11\,pp gap; a 10{,}000-iteration permutation test confirms $p \leq 10^{-4}$ for all boundary comparisons (Benjamini-Hochberg $q_{\max} = 0.003$ across $m{=}30$ tests; Appendix~\ref{sec:bh_correction}).
26	A Youden's J analysis independently validates this choice: the optimal threshold separating boundary from non-boundary AUC values falls at $\theta^*{=}0.605$ ($J{=}1.0$ at config level; $J{=}0.88$ at fold level), placing $\theta{=}0.60$ within the optimal interval $(0.595, 0.611)$~\cite{youden1950index}.
27	We select $\theta$ at this discontinuity because our goal is to identify a natural gap in discriminability rather than to maximize classification performance.
28	$\Kempirical{=}2$ is stable across $\theta \in [0.575, 0.625]$ for all but one marginal configuration (Table~\ref{tab:kstar_ci_extended}); only at extremes does $\Kempirical$ shift ($\theta{=}0.55$: $\Kempirical{=}3$ for Qwen-rewrite; $\theta{=}0.70$: $\Kempirical{=}1$).
29	The downstream filtering evaluation (Section~\ref{sec:filtering}) uses OBD without re-optimizing $\theta$, avoiding circularity.
30	To guard against circularity, we perform leave-one-family-out (LOFO) cross-validation: $\theta$ is derived from five architecture families and evaluated on the held-out sixth.
31	Including Gemma-2-2B narrows the consensus range to $\hat{\theta} \in [0.57, 0.59]$; 8/10 held-out predictions match the full-data $\Kempirical$ (mismatches: Qwen-rewrite mode effect; Gemma-2-2B $\Kempirical_{\hat{\theta}}{=}2$ vs.\ $\Kempirical_{0.60}{=}1$).
32	A separate non-Qwen held-out check (consensus $(0.54, 0.58]$, validated on three Qwen configs) confirms $\theta$ is not overfit to the scorer family.
33	$\theta{=}0.60$ sits above both ranges, yielding reliable lower bounds (Appendix~\ref{sec:theta_lofo}).
34	
35	
36	\subsection{Features and Classifier}
37	\label{sec:features}
38	
39	Each document is characterized by a 15-dimensional feature vector spanning four groups: \emph{surprisal moments} (mean, std, skewness, kurtosis; 4~dims), \emph{surprisal derivatives} (mean and std of first- and second-order differences, plus first-order skewness; 5~dims), \emph{vocabulary diversity} (type-token ratio, hapax legomena ratio, self-BLEU; 3~dims), and \emph{frequency tail statistics} (frequency kurtosis, entropy, rare token fraction; 3~dims).
40	All features are computed from token-level surprisal values via an external scorer model (Table~\ref{tab:s5_features}).
41	Self-BLEU is computed within each CV fold to prevent leakage; removing it reduces mean $\auc_{1v2}$ by ${<}\,1$\,pp ($\Kempirical$ unchanged; Table~\ref{tab:selfbleu_ablation}).
42	Hand-crafted features enable cross-generator transfer and permit attribution of discriminative power to specific text properties.
43	These features serve as empirically validated proxies for distributional shift across generations, rather than direct measures of mutual information; the monotonic AUC decay observed across all configurations (Table~\ref{tab:kstar_ci}) provides post-hoc validation.
44	
45	We use \emph{Ordinal Binary Decomposition} (OBD), decomposing the $(K{+}1)$-class problem into $K$ cumulative binary sub-classifiers, each estimating $P(\text{depth} > k \mid \mathbf{x})$ via LightGBM~\cite{ke2017lightgbm} (hyperparameters in Table~\ref{tab:s6_lgbm_params}); OBD achieves lower MAE than multiclass LightGBM (0.984 vs.\ 1.016) and superior pairwise $\auc$ (0.6095 vs.\ 0.4883 for ordinal logistic regression).
46	
47	\subsection{Experimental Setup}
48	\label{sec:experimental_setup}
49	
50	We evaluate ten configurations spanning six architecture families (1B--14B; Table~\ref{tab:setup}), each generating $K{=}5$ depth levels from 5{,}000 C4~\cite{raffel2020t5} seeds (256 tokens; 30{,}000 documents per configuration).
51	Default decoding: nucleus $p{=}0.95$, $T{=}1.0$; ablation covers greedy, $T{=}0.7$, and $T{=}1.2$.
52	Continuation mode truncates seeds to 128 tokens and extends to 256; rewrite mode paraphrases the full text.
53	Evaluation: 5-fold GroupKFold cross-validation grouped by seed document; pairwise $\auc$ as primary metric.
54	
55	\begin{table}[t]
56	\centering
57	\small
58	\caption{Experimental configurations for depth-chain generation. \textbf{Config}: shorthand identifier; \textbf{Model}: architecture and parameter count; \textbf{Mode}: generation strategy (continuation or rewrite); $N$: number of seed documents per depth level.}
59	\label{tab:setup}
60	\resizebox{\columnwidth}{!}{%
61	\begin{tabular}{llcc}
62	\toprule
63	\textbf{Config} & \textbf{Model} & \textbf{Mode} & $N$ \\
64	\midrule
65	Qwen-rw   & Qwen2.5-1.5B-Instruct & Rewrite & 5{,}000 \\
66	Qwen-cont & Qwen2.5-1.5B-Instruct & Continuation & 5{,}000 \\
67	Qwen-base & Qwen2.5-1.5B          & Continuation & 5{,}000 \\
68	Pythia    & Pythia-1.4B            & Continuation & 5{,}000 \\
69	OLMo      & OLMo-1B               & Continuation & 5{,}000 \\
70	Gemma     & Gemma-2-2B            & Continuation & 5{,}000 \\
71	Qwen-7B   & Qwen2.5-7B            & Continuation & 5{,}000 \\
72	Qwen-14B  & Qwen2.5-14B           & Continuation & 5{,}000 \\
73	LLaMA-8B  & LLaMA-3.1-8B          & Continuation & 5{,}000 \\
74	Mistral   & Mistral-7B            & Continuation & 5{,}000 \\
75	\bottomrule
76	\end{tabular}}
77	\end{table}
78	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c03a48f0-ae62-497e-b52a-32efc555e9d6",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "ce3a8057-ee8f-4f59-9531-ab59623d027a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Problem Formulation}\n\\label{sec:formulation}\n\nA generation operator $G_\\delta$ (LLM + decoding strategy $\\delta$) produces successive generations $X \\to Y_1 \\to \\cdots \\to Y_K$, where $Y_k = G_\\delta(Y_{k-1})$ and $Y_0 \\triangleq X$ (Figure~\\ref{fig:pipeline}).\nThis sequence forms a Markov chain.\nBy the Data Processing Inequality, $I(X; Y_1) \\geq I(X; Y_2) \\geq \\cdots \\geq 0$: the original signal degrades monotonically.\nTogether with Markov chain convergence, this implies a finite $\\Ktheory$ beyond which adjacent generations become indistinguishable; DPI motivates finite $\\Ktheory$ but does not formally guarantee or bound it.\nSpecifically, DPI constrains the cumulative divergence from the seed text; the adjacent-pair convergence that determines $\\Kempirical$ follows from the chain's approach to its stationary distribution~\\cite{levin2017markov}, where successive transition distributions become indistinguishable.\nThe actual saturation depth must therefore be measured empirically.\n\nWe define the operational lower bound $K^*_{\\text{empirical}}$ (hereafter $\\Kempirical$), where $S$ denotes the feature set (specified in Section~\\ref{sec:features}):\n\\begin{equation}\n  \\Kempirical = \\max\\!\\bigl\\{k \\!\\geq\\! 1 : \\mathrm{CI}_{\\mathrm{low}}(\\auc_{j\\text{-}1,j}) > \\theta,\\ \\forall j \\!\\leq\\! k\\bigr\\},\n  \\label{eq:kstar}\n\\end{equation}\nwhere $\\mathrm{CI}_{\\mathrm{low}}(\\auc_{k-1,k})$ is the lower bound of a 95\\% bootstrap confidence interval (1{,}000 resamples\\footnote{We use 1{,}000 resamples as the default for computational efficiency; arXiv cross-scorer CIs (Table~\\ref{tab:arxiv_crossscorer_ci}) use 10{,}000 to achieve tighter bounds at marginal boundaries where sub-pp differences determine the $\\Kempirical{=}2$ vs.\\ $\\Kempirical{=}3$ verdict.}) over the pairwise AUC (Area Under the ROC Curve) between depths $k{-}1$ and $k$, and $\\theta = 0.60$ is a post-hoc operational threshold (motivated below).\nThis criterion ensures that $\\Kempirical$ reflects statistically robust discriminability; the $\\forall j \\leq k$ constraint is naturally satisfied because $\\auc_{k,k+1}$ decreases monotonically above $\\theta$ across all tested configurations (Table~\\ref{tab:kstar_ci}).\nWhile non-monotonic $\\auc_{k,k+1}$ is theoretically possible if intermediate generations traverse a high-entropy transient region, we observe strict monotonicity above $\\theta$ across all 37 configurations (Table~\\ref{tab:kstar_ci_extended}).\n$\\Kempirical$ is jointly conditioned on the feature set and $\\theta$; the domain ordering is stable across $\\theta \\in [0.575, 0.65]$ (Section~\\ref{sec:kstar_boundary}). We verify that non-boundary CI upper bounds fall below $\\theta$.\n\n\\paragraph{Threshold choice.}\nWe set $\\theta{=}0.60$ at the empirical AUC discontinuity (Figure~\\ref{fig:kstar_theta}): 1v2 values cluster at $0.61$--$0.70$ while 2v3 values cluster at $0.55$--$0.59$, creating a ${\\sim}$5--11\\,pp gap; a 10{,}000-iteration permutation test confirms $p \\leq 10^{-4}$ for all boundary comparisons (Benjamini-Hochberg $q_{\\max} = 0.003$ across $m{=}30$ tests; Appendix~\\ref{sec:bh_correction}).\nA Youden's J analysis independently validates this choice: the optimal threshold separating boundary from non-boundary AUC values falls at $\\theta^*{=}0.605$ ($J{=}1.0$ at config level; $J{=}0.88$ at fold level), placing $\\theta{=}0.60$ within the optimal interval $(0.595, 0.611)$~\\cite{youden1950index}.\nWe select $\\theta$ at this discontinuity because our goal is to identify a natural gap in discriminability rather than to maximize classification performance.\n$\\Kempirical{=}2$ is stable across $\\theta \\in [0.575, 0.625]$ for all but one marginal configuration (Table~\\ref{tab:kstar_ci_extended}); only at extremes does $\\Kempirical$ shift ($\\theta{=}0.55$: $\\Kempirical{=}3$ for Qwen-rewrite; $\\theta{=}0.70$: $\\Kempirical{=}1$).\nThe downstream filtering evaluation (Section~\\ref{sec:filtering}) uses OBD without re-optimizing $\\theta$, avoiding circularity.\nTo guard against circularity, we perform leave-one-family-out (LOFO) cross-validation: $\\theta$ is derived from five architecture families and evaluated on the held-out sixth.\nIncluding Gemma-2-2B narrows the consensus range to $\\hat{\\theta} \\in [0.57, 0.59]$; 8/10 held-out predictions match the full-data $\\Kempirical$ (mismatches: Qwen-rewrite mode effect; Gemma-2-2B $\\Kempirical_{\\hat{\\theta}}{=}2$ vs.\\ $\\Kempirical_{0.60}{=}1$).\nA separate non-Qwen held-out check (consensus $(0.54, 0.58]$, validated on three Qwen configs) confirms $\\theta$ is not overfit to the scorer family.\n$\\theta{=}0.60$ sits above both ranges, yielding reliable lower bounds (Appendix~\\ref{sec:theta_lofo}).\n\n\n\\subsection{Features and Classifier}\n\\label{sec:features}\n\nEach document is characterized by a 15-dimensional feature vector spanning four groups: \\emph{surprisal moments} (mean, std, skewness, kurtosis; 4~dims), \\emph{surprisal derivatives} (mean and std of first- and second-order differences, plus first-order skewness; 5~dims), \\emph{vocabulary diversity} (type-token ratio, hapax legomena ratio, self-BLEU; 3~dims), and \\emph{frequency tail statistics} (frequency kurtosis, entropy, rare token fraction; 3~dims).\nAll features are computed from token-level surprisal values via an external scorer model (Table~\\ref{tab:s5_features}).\nSelf-BLEU is computed within each CV fold to prevent leakage; removing it reduces mean $\\auc_{1v2}$ by ${<}\\,1$\\,pp ($\\Kempirical$ unchanged; Table~\\ref{tab:selfbleu_ablation}).\nHand-crafted features enable cross-generator transfer and permit attribution of discriminative power to specific text properties.\nThese features serve as empirically validated proxies for distributional shift across generations, rather than direct measures of mutual information; the monotonic AUC decay observed across all configurations (Table~\\ref{tab:kstar_ci}) provides post-hoc validation.\n\nWe use \\emph{Ordinal Binary Decomposition} (OBD), decomposing the $(K{+}1)$-class problem into $K$ cumulative binary sub-classifiers, each estimating $P(\\text{depth} > k \\mid \\mathbf{x})$ via LightGBM~\\cite{ke2017lightgbm} (hyperparameters in Table~\\ref{tab:s6_lgbm_params}); OBD achieves lower MAE than multiclass LightGBM (0.984 vs.\\ 1.016) and superior pairwise $\\auc$ (0.6095 vs.\\ 0.4883 for ordinal logistic regression).\n\n\\subsection{Experimental Setup}\n\\label{sec:experimental_setup}\n\nWe evaluate ten configurations spanning six architecture families (1B--14B; Table~\\ref{tab:setup}), each generating $K{=}5$ depth levels from 5{,}000 C4~\\cite{raffel2020t5} seeds (256 tokens; 30{,}000 documents per configuration).\nDefault decoding: nucleus $p{=}0.95$, $T{=}1.0$; ablation covers greedy, $T{=}0.7$, and $T{=}1.2$.\nContinuation mode truncates seeds to 128 tokens and extends to 256; rewrite mode paraphrases the full text.\nEvaluation: 5-fold GroupKFold cross-validation grouped by seed document; pairwise $\\auc$ as primary metric.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Experimental configurations for depth-chain generation. \\textbf{Config}: shorthand identifier; \\textbf{Model}: architecture and parameter count; \\textbf{Mode}: generation strategy (continuation or rewrite); $N$: number of seed documents per depth level.}\n\\label{tab:setup}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Config} & \\textbf{Model} & \\textbf{Mode} & $N$ \\\\\n\\midrule\nQwen-rw   & Qwen2.5-1.5B-Instruct & Rewrite & 5{,}000 \\\\\nQwen-cont & Qwen2.5-1.5B-Instruct & Continuation & 5{,}000 \\\\\nQwen-base & Qwen2.5-1.5B          & Continuation & 5{,}000 \\\\\nPythia    & Pythia-1.4B            & Continuation & 5{,}000 \\\\\nOLMo      & OLMo-1B               & Continuation & 5{,}000 \\\\\nGemma     & Gemma-2-2B            & Continuation & 5{,}000 \\\\\nQwen-7B   & Qwen2.5-7B            & Continuation & 5{,}000 \\\\\nQwen-14B  & Qwen2.5-14B           & Continuation & 5{,}000 \\\\\nLLaMA-8B  & LLaMA-3.1-8B          & Continuation & 5{,}000 \\\\\nMistral   & Mistral-7B            & Continuation & 5{,}000 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n",
      "numLines": 78,
      "startLine": 1,
      "totalLines": 78
    }
  },
  "sourceToolAssistantUUID": "c03a48f0-ae62-497e-b52a-32efc555e9d6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-21T06:34:49.324Z_

<details open><summary>🔧 Tool call — Read · `toolu_01VnQi9iQkV3o2VhpsedHS54`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ce3a8057-ee8f-4f59-9531-ab59623d027a",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "22330d9d-9da8-4d29-a19f-c53cf41d597c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 27 · 2026-05-21T06:34:49.330Z_

<details><summary>↩ Tool result · `toolu_01VnQi9iQkV3o2VhpsedHS54`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Model collapse and recursive degradation.}
5	Iterative training on model outputs causes tail-distribution degradation~\cite{shumailov2024collapse, alemohammad2024selfconsuming, dohmatob2024model, dohmatob2024demystified, dohmatob2025strong, seddik2024how}, diversity contraction~\cite{guo2024curious, padmakumar2024writing, briesch2023selfconsuming}, and predictable convergence~\cite{bertrand2024stability, schaeffer2025position, kazdan2025collapse, gerstgrasser2024model, shi2025collapse, xu2025probabilistic}.
6	Surplexity~\cite{gambetta2024surplexity} provides a single collapse indicator; Wang et al.~\cite{wang2026contamination} provide theoretical guarantees for contaminated recursive training; Fu et al.~\cite{fu2025theoretical} offer a theoretical perspective on preventing collapse in self-consuming loops; curation can mitigate collapse~\cite{amin2025escaping}, connecting to Section~\ref{sec:filtering}.
7	This literature establishes convergence but provides no per-text depth measurement and does not predict domain-dependent saturation or the prompt-chain vs.\ retrain-chain gap ($\Kempirical{=}2$ vs.\ $7$).
8	
9	\paragraph{Iterative generation dynamics.}
10	Mohamed et al.~\cite{mohamed2025telephone} study how information distorts across iterative generation chains, finding that degradation accumulates with chain length.
11	Geng et al.~\cite{geng2026markovian} formalize iterative generation as Markovian chains and show that outputs converge to small cycle sets.
12	Wang et al.~\cite{wang2025attractor} show that successive paraphrasing converges to low-period attractor cycles, suggesting a dynamical-systems view; the attractor entry depth may correspond to the discrimination boundary, though this parallel remains suggestive.
13	Gillman et al.~\cite{gillman2024selfcorrecting} propose self-correcting mechanisms for self-consuming loops.
14	Shahriar et al.~\cite{shahriar2025erosion} report a 25.4\% decline in detection performance after five paraphrasing rounds, consistent with our finding that discrimination collapses within two to three generations.
15	While these works characterize \emph{whether and when} outputs converge (a dynamical-systems question), none provides a per-text operational depth estimate; $\Kempirical$ measures \emph{at which depth} adjacent generations become statistically indistinguishable (an operational discrimination question).
16	
17	\paragraph{Beyond binary detection.}
18	Binary detectors~\cite{gehrmann2019gltr, mitchell2023detectgpt, bao2024fast, yang2024dnagpt, hans2024binoculars, verma2024ghostbuster, basani2026diveye, zhang2024minkpp, hu2023radar, tulchinskii2024intrinsic} achieve strong human-vs.-machine separation but produce no depth estimate; recent extensions address collaboration degree~\cite{cheng2025beyond}, contamination hierarchies~\cite{mehta2025beyond}, multigenerator benchmarks~\cite{wang2024semeval}, fine-grained creator-editor attribution~\cite{li2026beyond}, and robustness under paraphrasing~\cite{sadasivan2023detect, krishna2023paraphrasing}; CoDeC~\cite{zawalski2026codec} addresses contamination via membership inference.
19	None estimates recursive generation depth; watermarking~\cite{kirchenbauer2023watermark} embeds signals at generation time but does not apply to text already in the wild.
20	
21	\paragraph{Distributional quality metrics.}
22	MAUVE~\cite{pillutla2021mauve, pillutla2023mauve} measures corpus-level distributional closeness but not multi-generational degradation; $\Kempirical$ complements such metrics by localizing per-text depth saturation.
23	
24	\paragraph{Data selection and curation.}
25	DSIR~\cite{xie2023dsir}, D4~\cite{tirumala2023d4}, DoReMi~\cite{xie2023doremi}, and FineWeb~\cite{penedo2024fineweb} address corpus quality through domain-aware filtering but are depth-agnostic; \citet{drayson2025} combined binary detection with importance resampling ($\Kstar{=}1$); \citet{oren2024proving} address pre-training contamination without depth-granular resolution.
26	
27	\paragraph{Ordinal classification and probing.}
28	Our surprisal features build on information-theoretic processing cost~\cite{hale2001surprisal, levy2008expectation}, repurposed to track generational degradation.
29	Our OBD classifier follows Frank \& Hall's~\cite{frank2001ordinal} binary decomposition; CORAL~\cite{cao2020coral} provides a rank-consistent neural alternative.
30	Our neural probe extends probing~\cite{alain2017understanding, belinkov2022probing} to the discrimination boundary.
31	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "22330d9d-9da8-4d29-a19f-c53cf41d597c",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "3ee20d0b-eea5-487b-b8ed-1790898dd564",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Model collapse and recursive degradation.}\nIterative training on model outputs causes tail-distribution degradation~\\cite{shumailov2024collapse, alemohammad2024selfconsuming, dohmatob2024model, dohmatob2024demystified, dohmatob2025strong, seddik2024how}, diversity contraction~\\cite{guo2024curious, padmakumar2024writing, briesch2023selfconsuming}, and predictable convergence~\\cite{bertrand2024stability, schaeffer2025position, kazdan2025collapse, gerstgrasser2024model, shi2025collapse, xu2025probabilistic}.\nSurplexity~\\cite{gambetta2024surplexity} provides a single collapse indicator; Wang et al.~\\cite{wang2026contamination} provide theoretical guarantees for contaminated recursive training; Fu et al.~\\cite{fu2025theoretical} offer a theoretical perspective on preventing collapse in self-consuming loops; curation can mitigate collapse~\\cite{amin2025escaping}, connecting to Section~\\ref{sec:filtering}.\nThis literature establishes convergence but provides no per-text depth measurement and does not predict domain-dependent saturation or the prompt-chain vs.\\ retrain-chain gap ($\\Kempirical{=}2$ vs.\\ $7$).\n\n\\paragraph{Iterative generation dynamics.}\nMohamed et al.~\\cite{mohamed2025telephone} study how information distorts across iterative generation chains, finding that degradation accumulates with chain length.\nGeng et al.~\\cite{geng2026markovian} formalize iterative generation as Markovian chains and show that outputs converge to small cycle sets.\nWang et al.~\\cite{wang2025attractor} show that successive paraphrasing converges to low-period attractor cycles, suggesting a dynamical-systems view; the attractor entry depth may correspond to the discrimination boundary, though this parallel remains suggestive.\nGillman et al.~\\cite{gillman2024selfcorrecting} propose self-correcting mechanisms for self-consuming loops.\nShahriar et al.~\\cite{shahriar2025erosion} report a 25.4\\% decline in detection performance after five paraphrasing rounds, consistent with our finding that discrimination collapses within two to three generations.\nWhile these works characterize \\emph{whether and when} outputs converge (a dynamical-systems question), none provides a per-text operational depth estimate; $\\Kempirical$ measures \\emph{at which depth} adjacent generations become statistically indistinguishable (an operational discrimination question).\n\n\\paragraph{Beyond binary detection.}\nBinary detectors~\\cite{gehrmann2019gltr, mitchell2023detectgpt, bao2024fast, yang2024dnagpt, hans2024binoculars, verma2024ghostbuster, basani2026diveye, zhang2024minkpp, hu2023radar, tulchinskii2024intrinsic} achieve strong human-vs.-machine separation but produce no depth estimate; recent extensions address collaboration degree~\\cite{cheng2025beyond}, contamination hierarchies~\\cite{mehta2025beyond}, multigenerator benchmarks~\\cite{wang2024semeval}, fine-grained creator-editor attribution~\\cite{li2026beyond}, and robustness under paraphrasing~\\cite{sadasivan2023detect, krishna2023paraphrasing}; CoDeC~\\cite{zawalski2026codec} addresses contamination via membership inference.\nNone estimates recursive generation depth; watermarking~\\cite{kirchenbauer2023watermark} embeds signals at generation time but does not apply to text already in the wild.\n\n\\paragraph{Distributional quality metrics.}\nMAUVE~\\cite{pillutla2021mauve, pillutla2023mauve} measures corpus-level distributional closeness but not multi-generational degradation; $\\Kempirical$ complements such metrics by localizing per-text depth saturation.\n\n\\paragraph{Data selection and curation.}\nDSIR~\\cite{xie2023dsir}, D4~\\cite{tirumala2023d4}, DoReMi~\\cite{xie2023doremi}, and FineWeb~\\cite{penedo2024fineweb} address corpus quality through domain-aware filtering but are depth-agnostic; \\citet{drayson2025} combined binary detection with importance resampling ($\\Kstar{=}1$); \\citet{oren2024proving} address pre-training contamination without depth-granular resolution.\n\n\\paragraph{Ordinal classification and probing.}\nOur surprisal features build on information-theoretic processing cost~\\cite{hale2001surprisal, levy2008expectation}, repurposed to track generational degradation.\nOur OBD classifier follows Frank \\& Hall's~\\cite{frank2001ordinal} binary decomposition; CORAL~\\cite{cao2020coral} provides a rank-consistent neural alternative.\nOur neural probe extends probing~\\cite{alain2017understanding, belinkov2022probing} to the discrimination boundary.\n",
      "numLines": 31,
      "startLine": 1,
      "totalLines": 31
    }
  },
  "sourceToolAssistantUUID": "22330d9d-9da8-4d29-a19f-c53cf41d597c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-21T06:34:49.865Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FwUxTCR4rqBjZj31wLRZk4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3ee20d0b-eea5-487b-b8ed-1790898dd564",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "a49c7d99-1bca-4f88-9dc8-f6f2cd084bc5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 29 · 2026-05-21T06:34:49.872Z_

<details><summary>↩ Tool result · `toolu_01FwUxTCR4rqBjZj31wLRZk4`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate on ten configurations spanning six families (1B--14B; all continuation mode except where noted) using OBD-LightGBM with the 15-dimensional feature set (Section~\ref{sec:method}; 5{,}000 texts per depth; Appendix~\ref{sec:power_curve}).
5	
6	%% ====================================================================
7	\subsection{\texorpdfstring{$\Kempirical \leq 2$}{K*<=2} Across Model Configurations (C4)}
8	\label{sec:kstar_boundary}
9	
10	\begin{table*}[t]
11	\centering
12	\small
13	\caption{Pairwise $\auc$ for adjacent depth pairs with bootstrap 95\% CIs (1{,}000 resamples) and permutation $p$-values.
14	$\Kempirical = 2$ requires 1v2 CI lower $> \theta{=}0.60$ and 2v3 CI lower $\leq \theta$ (Eq.~\ref{eq:kstar}).
15	$\leq$1.5B models use self-scoring; 7B/14B use Qwen-1.5B scorer ($^\ddagger$).
16	Extended results in Table~\ref{tab:kstar_ci_extended}.}
17	\label{tab:kstar_ci}
18	\begin{tabular}{lcccccccccc}
19	\toprule
20	 & \multicolumn{2}{c}{Qwen-rw\rlap{$^\dagger$}} & \multicolumn{2}{c}{Pythia} & \multicolumn{2}{c}{OLMo} & \multicolumn{2}{c}{Qwen-cont} & \multicolumn{2}{c}{Qwen-7B\rlap{$^\ddagger$}} \\
21	\cmidrule(lr){2-3}\cmidrule(lr){4-5}\cmidrule(lr){6-7}\cmidrule(lr){8-9}\cmidrule(lr){10-11}
22	 & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI \\
23	\midrule
24	0v1 & .9956 & & .9932 & & .9970 & & .9971 & & .9638 & [.961,\,.967] \\
25	1v2 & .6955 & [.686,\,.704]\rlap{$^*$} & .6539 & [.645,\,.663]\rlap{$^*$} & .6145 & [.605,\,.625]\rlap{$^*$} & .6112 & [.602,\,.621]\rlap{$^*$} & .6168 & [.608,\,.626]\rlap{$^*$} \\
26	2v3 & .5893 & [.580,\,.599] & .5514 & [.542,\,.563] & .5496 & [.540,\,.560] & .5609 & [.551,\,.571] & .5492 & [.539,\,.559] \\
27	3v4 & .5435 & & .5152 & & .5091 & & .5409 & & .5276 & \\
28	4v5 & .5340 & & .5136 & & .5045 & & .5141 & & .5085 & \\
29	\bottomrule
30	\multicolumn{11}{l}{\footnotesize $^*$Permutation $p \leq 10^{-4}$ for all 1v2 comparisons shown (BH-corrected $q_{\max} = 0.003$).} \\
31	\multicolumn{11}{l}{\footnotesize $^\dagger$Rewrite mode (ablation); excluded from continuation-mode $\Kempirical$ claim.} \\
32	\multicolumn{11}{l}{\footnotesize $^\ddagger$Generator: Qwen2.5-7B (fp16); scorer: Qwen2.5-1.5B.}
33	\end{tabular}
34	\end{table*}
35	
36	Table~\ref{tab:kstar_ci} and Figure~\ref{fig:kstar_theta}(a) show $\Kempirical{=}2$ at $\theta{=}0.60$ for 7/9 continuation-mode C4 configurations across four of six tested architecture families (4 Qwen + 3 non-Qwen; 1v2 $\auc$ range: 0.6112--0.6539; all CI lower bounds $> \theta$; permutation $p \leq 10^{-4}$).
37	The 1v2 vs.\ 2v3 AUC gap ranges from 5.0 to 10.6\,pp across configurations, exhibiting a sharp cliff at the boundary: all 2v3 values fall below $\theta$ while 1v2 values remain 1--10\,pp above it.
38	Gemma-2-2B and Mistral-7B are competence-limited at $\Kempirical{=}1$ (1v2 $\auc$: 0.598, CI $[0.588, 0.608]$; and 0.594, respectively): both achieve near-perfect 0v1 separation but fail to sustain 1v2 above $\theta$.
39	Among the remaining non-Qwen families, Pythia and OLMo yield clear $\Kempirical{=}2$; LLaMA-3.1-8B is borderline (1v2 $\auc = 0.6123$, CI lower $= 0.603$).
40	An independent F1@0.50 analysis confirms the same boundary for all configurations (Appendix~\ref{sec:f1_validation}).
41	All four decoding strategies yield $\Kempirical{=}2$ (Table~\ref{tab:s2_decoding}), and $\Kempirical{=}2$ persists from 1.5B through 14B (Appendix~\ref{sec:boundary_extended}).
42	
43	\begin{figure*}[t]
44	\centering
45	\includegraphics[width=\textwidth]{figures/fig_kstar_theta.pdf}
46	\caption{(a) Pairwise $\auc$ decay across depth pairs for model-mode configurations (solid) and decoding strategies (dashed); horizontal dashed line marks $\theta = 0.60$; AUC computed on held-out folds. (b) $\Kempirical(\theta)$ sensitivity: all configurations yield $\Kempirical{=}2$ at $\theta{=}0.60$; at $\theta{=}0.70$, all drop to $\Kempirical{=}1$.}
47	\label{fig:kstar_theta}
48	\end{figure*}
49	
50	Figure~\ref{fig:kstar_theta} shows $\Kempirical$ as a function of $\theta$: web text $\Kempirical{=}2$ is stable across $\theta \in [0.575, 0.625]$, with transitions to $\Kempirical{=}3$ at $\theta{=}0.55$ (Qwen-rewrite) and $\Kempirical{=}1$ at $\theta{=}0.70$; the domain ordering is preserved across the full range (Table~\ref{tab:theta_sensitivity}).
51	A changepoint analysis (PELT~\cite{killick2012optimal}) provides complementary, threshold-free evidence: exact agreement is 18/37 (49\%; linear weighted $\kappa{=}0.42$, moderate agreement), rising to 35/37 (95\%) within $\pm 1$; PELT is systematically conservative ($\Kempirical_{\text{PELT}} \leq \Kempirical_{\text{OBD}}$ in all 19 disagreements; Appendix~\ref{sec:changepoint_validation}).
52	We do not rely on changepoint agreement for $\Kempirical$ determination.
53	
54	\paragraph{Margin stratification.}
55	To assess the robustness of individual $\Kempirical{=}2$ assignments, we stratify the seven continuation-mode configurations by their margin above $\theta$ (CI lower $-$ $\theta$; Table~\ref{tab:kstar_ci_extended}).
56	Three configurations across three families show confident margins exceeding 1\,pp: Pythia-1.4B (4.5\,pp), Qwen-base (1.7\,pp), and Qwen-14B (1.2\,pp).
57	Four have marginal support (${<}\,1$\,pp): Qwen-7B (0.8\,pp), OLMo-1B (0.5\,pp), LLaMA-8B (0.3\,pp), and Qwen-cont (0.2\,pp); the last drops to $\Kempirical{=}1$ under cross-scorer control (Section~\ref{sec:transfer}).
58	We emphasize that $\Kempirical$ is determined by bootstrap CI (Eq.~\ref{eq:kstar}), not by permutation $p$-values, which serve as supplementary validation.
59	The $\theta$-invariant domain ordering (Section~\ref{sec:cross_domain}) is supported by the confident configurations alone and does not depend on marginal cases.
60	
61	%% ====================================================================
62	\subsection{Cross-Model Transfer and Its Limits}
63	\label{sec:transfer}
64	
65	\begin{figure}[t]
66	\centering
67	\includegraphics[width=0.85\columnwidth]{figures/fig3_transfer_heatmap.pdf}
68	\caption{Cross-model transfer heatmap. Each cell shows 6-class ordinal accuracy when trained on the row model and tested on the column model, divided by in-domain accuracy (retention rate). Pythia$\leftrightarrow$OLMo: 90--92\%; Qwen-rewrite$\to$continuation: 61--63\%.}
69	\label{fig:transfer_heatmap}
70	\end{figure}
71	
72	Aggregate transfer is strong: continuation-mode classifiers retain 80--92\% ordinal accuracy across generators at $\leq$1.5B (Figure~\ref{fig:transfer_heatmap}; Table~\ref{tab:s1_transfer}), and 96--100\% mean pairwise AUC at 7B (Appendix~\ref{sec:7b_transfer}).
73	However, boundary-level transfer is fragile: at 7B, 4/6 off-diagonal 1v2 pairs fall below $\theta$, so $\Kempirical{=}2$ assignments do not transfer at the boundary even as overall discriminability improves with scale.
74	Qwen-rewrite classifiers transfer poorly (61--63\%), consistent with reliance on mode-specific artifacts.
75	
76	\paragraph{Cross-scorer validation.}
77	Replacing the self-scorer with Pythia-1.4B or OLMo-1B preserves feature rankings ($\rho > 0.90$; Table~\ref{tab:crossscorer}) and $\Kempirical$ in 20/22 cross-scorer configurations on C4 and arXiv; the two exceptions are the most marginal boundary configurations (AUC within 0.002 of $\theta$).
78	Notably, the most marginal self-scored configuration (Qwen-cont, CI lower $= 0.602$, margin $0.2$\,pp) drops to $\Kempirical{=}1$ under Pythia and OLMo scoring (1v2 AUC $= 0.592$/$0.586$), reducing the continuation-mode count from 7/9 to 6/9 under strict cross-scorer control.
79	For arXiv, Pythia-1.4B cross-scoring preserves $\Kempirical{=}3$ for 3/4 generators (2v3 $\auc$: 0.608--0.632); Qwen-7B drops to borderline $\Kempirical{=}2$ ($\Delta = -2.7$\,pp; Table~\ref{tab:arxiv_crossscorer_ci}).
80	A three-way ANOVA confirms Depth-Pair dominates variance ($\eta^2_p = 0.998$; Scorer: $\eta^2_p = 0.192$; Table~\ref{tab:anova_crossscorer}); replacing the 1.5B scorer with Qwen2.5-7B preserves $\Kempirical$ identically ($\Delta\,\auc < 1$\,pp; Appendix~\ref{sec:scorer_scale}).
81	
82	%% ====================================================================
83	\subsection{Feature Ordering and Generation Mode}
84	\label{sec:feature_degradation}
85	\label{sec:generation_mode}
86	
87	Among continuation-mode models, single-feature $\auc$ rankings are highly correlated ($\rho \geq 0.85$; Table~\ref{tab:top_features}), with the top-3 (\texttt{surp\_d1\_std}, \texttt{surp\_std}, \texttt{surp\_d2\_std}) shared across families; no single subset of size ${<}8$ sustains $\Kempirical{=}2$ (Appendix~\ref{sec:feature_subset}), and surprisal dominates on arXiv while C4 relies on feature combinations (Appendix~\ref{sec:feature_ablation}).
88	Qwen-rewrite diverges ($\Delta = +8.4$\,pp), consistent with mode-specific artifacts; continuation mode is the canonical condition.
89	
90	%% ====================================================================
91	\subsection{Neural Probe}
92	\label{sec:neural_probe}
93	
94	A neural MLP probe on frozen encoder states (Table~\ref{tab:neural_probe_crossmodel}) raises $K^*_{\text{neural}}$ to 3 for Qwen (2v3 $\auc = 0.616$) but not Pythia or OLMo ($\auc_{2v3}$: 0.596, 0.589), reflecting self-familiarity artifacts; the 15D statistical features yield consistent $\Kempirical = 2$ across all families.
95	
96	\paragraph{Fine-tuned DeBERTa upper bound.}
97	DeBERTa-v3-base ordinal classifiers raise 1v2 $\auc$ over LightGBM at all three scales (1.5B: $0.705$ vs.\ $0.626$; 14B: $0.678$ vs.\ $0.621$; 32B: $0.694$ vs.\ $0.618$) yet preserve $\Kempirical{=}2$ (all 2v3 CI lower ${<}\,\theta$; Table~\ref{tab:deberta_comparison}); LightGBM shifts by ${<}\,0.5$\,pp across 1.5B--32B.
98	The classifier gap reveals a feature-set-dependent two-tier structure: zero on C4 and Code (DeBERTa $\Kempirical{=}2$, matching OBD), but $+2$ on Wikipedia (DeBERTa $\Kempirical{=}3$; OLMo excluded) and $+1$ on arXiv (DeBERTa $\Kempirical{=}4$, 3v4 $\auc = 0.624$; Table~\ref{tab:deberta_arxiv}); cross-transfer on Wikipedia mirrors the OBD pattern ($\Kempirical{=}3$ drops to ${\sim}2$; Table~\ref{tab:wiki_deberta_transfer}).
99	The C4 result ($\Kempirical_{\text{DeBERTa}} = \Kempirical_{\text{OBD}} = 2$) establishes a representation-independent boundary: even a 184M-parameter fine-tuned encoder cannot surpass $\Kempirical{=}2$ on web text.
100	The neural probe (Section~\ref{sec:neural_probe}), which uses frozen encoder representations with a linear head, provides an intermediate reference point between 15D statistics and full DeBERTa fine-tuning.
101	
102	\noindent\begin{minipage}{\columnwidth}
103	\centering
104	\footnotesize
105	\captionof{table}{DeBERTa-v3-base vs.\ LightGBM on C4 generations at three scales. Both classifiers yield $\Kempirical{=}2$ at 1.5B, 14B, and 32B.}
106	\label{tab:deberta_comparison}
107	\begin{tabular}{lccccc}
108	\toprule
109	& \textbf{0v1} & \textbf{1v2} & \textbf{2v3} & \textbf{3v4} & \textbf{4v5} \\
110	\midrule
111	LightGBM (1.5B) & ---  & .626 & .549 & ---  & --- \\
112	DeBERTa (1.5B)  & .992 & .705 & .599 & ---  & --- \\
113	\midrule
114	LightGBM (14B)  & .960 & .621 & .549 & .524 & --- \\
115	DeBERTa (14B)   & .994 & .678 & .590 & .565 & --- \\
116	\midrule
117	LightGBM (32B)  & .958 & .618 & .545 & .522 & .516 \\
118	DeBERTa (32B)   & .993 & .694 & .594 & .567 & .543 \\
119	\bottomrule
120	\end{tabular}
121	\end{minipage}
122	
123	%% ====================================================================
124	\subsection{Cross-Domain Variation}
125	\label{sec:cross_domain}
126	
127	To test whether $\Kempirical$ reflects domain structure or model identity, we extend evaluation to arXiv ($n{=}2{,}200$), Wikipedia ($n{=}5{,}000$), and Code ($n{=}5{,}000$) across six configurations spanning four families (Table~\ref{tab:domain_kstar}).
128	
129	\paragraph{arXiv ($\Kempirical{=}3$): five-model cross-validation.}
130	All five domain-competent models yield $\Kempirical{=}3$ (2v3 $\auc$: 0.6215--0.6545, all ${>}\,\theta$), reflecting formulaic features (LaTeX formatting, citation patterns) that degrade slowly and supply persistent depth signal across four families (1.4B--8B).
131	Removing LaTeX markup reduces 2v3 AUC by ${\sim}$1.8\,pp but preserves $\Kempirical{=}3$ (CI lower $= 0.610$; Table~\ref{tab:latex_ablation}).
132	OLMo-1B is a capacity failure (0v1 JSD $= 0.33$), not a counter-example; Mistral-7B provides the strongest domain-dependence evidence ($\Kempirical{=}1$ on C4 but $\Kempirical{=}3$ on arXiv).
133	The arXiv subset ($n{=}2{,}200$ per depth) is smaller than C4 ($n{=}5{,}000$); at equal sample size, wider bootstrap CIs shift borderline C4 configurations below $\theta$, yielding $\Kempirical{=}1$; the $\Kempirical{=}2$ verdict for these marginal C4 cases requires ${\geq}5{,}000$ samples.
134	
135	\paragraph{Wikipedia ($\Kempirical{=}1$): single-generation saturation.}
136	With cross-family scorer control, all six models yield $\Kempirical{=}1$ (1v2 $\auc$: 0.498--0.595, all below $\theta$): encyclopedic regularity provides minimal signal beyond the 0v1 boundary.
137	Same-family scoring inflates Qwen to $\Kempirical{=}2$ ($\Delta = +2.4$\,pp); cross-family scoring controls this bias (Appendix~\ref{sec:wiki_domain}).
138	
139	\paragraph{Code ($\Kempirical{=}1$--$2$): cross-modality confirmation.}
140	Python functions from CodeSearchNet~\cite{husain2019codesearchnet} ($n{=}5{,}000$) yield $\Kempirical{=}2$ for four models (1v2 $\auc$: 0.615--0.739; Table~\ref{tab:code_crossmodel_kstar}) with the same sharp 2v3 collapse as C4 (JSD ratio $11.7$--$13.5\times$); Pythia-1.4B is capacity-limited ($\Kempirical{=}1$, $\auc = 0.598$; cross-family scorer: $\Delta \leq 1.9$\,pp; Appendix~\ref{sec:code_domain}).
141	
142	\paragraph{Multi-source generator mixing.}
143	Multi-source pooling (three generators per domain; Appendix~\ref{sec:multi_source_details}) preserves domain-calibrated $\Kempirical$ across all four domains (C4 $\Kempirical{=}2$, unified 1v2 $\auc = 0.711$, generator identity $+0.010$ mean $\auc$ [range: $+0.001$, $+0.022$]; $\Kempirical$ unchanged in all eight configurations; arXiv $\Kempirical{=}3$; Code $\Kempirical{=}2$; Wikipedia $\Kempirical{=}1$), independently confirming the cross-scorer correction on Wikipedia.
144	
145	\noindent\begin{minipage}{\columnwidth}
146	\centering
147	\footnotesize
148	\captionof{table}{Domain $\times$ Model $\Kempirical$ matrix (scorer-controlled). Wikipedia values use cross-family scorer (Pythia-1.4B). $^*$OLMo arXiv: capacity failure. $^\dagger$Same-family scorer yields $\Kempirical{=}2$; controlled value shown. $^\ddagger$Borderline: Pythia CI upper $= 0.603$, Mistral CI lower $= 0.603$.}
149	\label{tab:domain_kstar}
150	\resizebox{\columnwidth}{!}{%
151	\begin{tabular}{lcccc}
152	\toprule
153	\textbf{Model} & \textbf{C4} & \textbf{Code} & \textbf{arXiv} & \textbf{Wikipedia} \\
154	\midrule
155	Qwen-1.5B    & 2 & 2 & 3 & 1$^\dagger$ \\
156	Qwen-7B      & 2 & 2 & 3 & 1$^\dagger$ \\
157	Pythia-1.4B  & 2 & 1$^\ddagger$ & 3 & 1 \\
158	OLMo-1B      & 2 & --- & 1$^*$ & 1 \\
159	Gemma-2-2B   & 1 & --- & --- & --- \\
160	LLaMA-3.1-8B & 2 & 2 & 3 & 1 \\
161	Mistral-7B   & 1 & 2$^\ddagger$ & 3 & 1 \\
162	\bottomrule
163	\end{tabular}}
164	\end{minipage}
165	
166	\paragraph{Summary.}
167	\label{sec:binary_confidence}
168	$\Kempirical{=}2$ at $\theta{=}0.60$ for web text holds across four of six families (1B--14B), four decoding strategies, and multi-source pools (Gemma-2-2B and Mistral-7B: $\Kempirical{=}1$; binary detectors: $K^*_{\text{binary}} \leq 1$, Table~\ref{tab:s9_binary_spearman}).
169	The domain ordering arXiv $>$ C4 $=$ Code $>$ Wikipedia is $\theta$-invariant; scale and architecture do not alter this ordering, confirming structural complexity as the primary determinant.
170	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a49c7d99-1bca-4f88-9dc8-f6f2cd084bc5",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "4159c868-65f1-44e3-820c-816972f32d0e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe evaluate on ten configurations spanning six families (1B--14B; all continuation mode except where noted) using OBD-LightGBM with the 15-dimensional feature set (Section~\\ref{sec:method}; 5{,}000 texts per depth; Appendix~\\ref{sec:power_curve}).\n\n%% ====================================================================\n\\subsection{\\texorpdfstring{$\\Kempirical \\leq 2$}{K*<=2} Across Model Configurations (C4)}\n\\label{sec:kstar_boundary}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Pairwise $\\auc$ for adjacent depth pairs with bootstrap 95\\% CIs (1{,}000 resamples) and permutation $p$-values.\n$\\Kempirical = 2$ requires 1v2 CI lower $> \\theta{=}0.60$ and 2v3 CI lower $\\leq \\theta$ (Eq.~\\ref{eq:kstar}).\n$\\leq$1.5B models use self-scoring; 7B/14B use Qwen-1.5B scorer ($^\\ddagger$).\nExtended results in Table~\\ref{tab:kstar_ci_extended}.}\n\\label{tab:kstar_ci}\n\\begin{tabular}{lcccccccccc}\n\\toprule\n & \\multicolumn{2}{c}{Qwen-rw\\rlap{$^\\dagger$}} & \\multicolumn{2}{c}{Pythia} & \\multicolumn{2}{c}{OLMo} & \\multicolumn{2}{c}{Qwen-cont} & \\multicolumn{2}{c}{Qwen-7B\\rlap{$^\\ddagger$}} \\\\\n\\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\\cmidrule(lr){6-7}\\cmidrule(lr){8-9}\\cmidrule(lr){10-11}\n & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI \\\\\n\\midrule\n0v1 & .9956 & & .9932 & & .9970 & & .9971 & & .9638 & [.961,\\,.967] \\\\\n1v2 & .6955 & [.686,\\,.704]\\rlap{$^*$} & .6539 & [.645,\\,.663]\\rlap{$^*$} & .6145 & [.605,\\,.625]\\rlap{$^*$} & .6112 & [.602,\\,.621]\\rlap{$^*$} & .6168 & [.608,\\,.626]\\rlap{$^*$} \\\\\n2v3 & .5893 & [.580,\\,.599] & .5514 & [.542,\\,.563] & .5496 & [.540,\\,.560] & .5609 & [.551,\\,.571] & .5492 & [.539,\\,.559] \\\\\n3v4 & .5435 & & .5152 & & .5091 & & .5409 & & .5276 & \\\\\n4v5 & .5340 & & .5136 & & .5045 & & .5141 & & .5085 & \\\\\n\\bottomrule\n\\multicolumn{11}{l}{\\footnotesize $^*$Permutation $p \\leq 10^{-4}$ for all 1v2 comparisons shown (BH-corrected $q_{\\max} = 0.003$).} \\\\\n\\multicolumn{11}{l}{\\footnotesize $^\\dagger$Rewrite mode (ablation); excluded from continuation-mode $\\Kempirical$ claim.} \\\\\n\\multicolumn{11}{l}{\\footnotesize $^\\ddagger$Generator: Qwen2.5-7B (fp16); scorer: Qwen2.5-1.5B.}\n\\end{tabular}\n\\end{table*}\n\nTable~\\ref{tab:kstar_ci} and Figure~\\ref{fig:kstar_theta}(a) show $\\Kempirical{=}2$ at $\\theta{=}0.60$ for 7/9 continuation-mode C4 configurations across four of six tested architecture families (4 Qwen + 3 non-Qwen; 1v2 $\\auc$ range: 0.6112--0.6539; all CI lower bounds $> \\theta$; permutation $p \\leq 10^{-4}$).\nThe 1v2 vs.\\ 2v3 AUC gap ranges from 5.0 to 10.6\\,pp across configurations, exhibiting a sharp cliff at the boundary: all 2v3 values fall below $\\theta$ while 1v2 values remain 1--10\\,pp above it.\nGemma-2-2B and Mistral-7B are competence-limited at $\\Kempirical{=}1$ (1v2 $\\auc$: 0.598, CI $[0.588, 0.608]$; and 0.594, respectively): both achieve near-perfect 0v1 separation but fail to sustain 1v2 above $\\theta$.\nAmong the remaining non-Qwen families, Pythia and OLMo yield clear $\\Kempirical{=}2$; LLaMA-3.1-8B is borderline (1v2 $\\auc = 0.6123$, CI lower $= 0.603$).\nAn independent F1@0.50 analysis confirms the same boundary for all configurations (Appendix~\\ref{sec:f1_validation}).\nAll four decoding strategies yield $\\Kempirical{=}2$ (Table~\\ref{tab:s2_decoding}), and $\\Kempirical{=}2$ persists from 1.5B through 14B (Appendix~\\ref{sec:boundary_extended}).\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig_kstar_theta.pdf}\n\\caption{(a) Pairwise $\\auc$ decay across depth pairs for model-mode configurations (solid) and decoding strategies (dashed); horizontal dashed line marks $\\theta = 0.60$; AUC computed on held-out folds. (b) $\\Kempirical(\\theta)$ sensitivity: all configurations yield $\\Kempirical{=}2$ at $\\theta{=}0.60$; at $\\theta{=}0.70$, all drop to $\\Kempirical{=}1$.}\n\\label{fig:kstar_theta}\n\\end{figure*}\n\nFigure~\\ref{fig:kstar_theta} shows $\\Kempirical$ as a function of $\\theta$: web text $\\Kempirical{=}2$ is stable across $\\theta \\in [0.575, 0.625]$, with transitions to $\\Kempirical{=}3$ at $\\theta{=}0.55$ (Qwen-rewrite) and $\\Kempirical{=}1$ at $\\theta{=}0.70$; the domain ordering is preserved across the full range (Table~\\ref{tab:theta_sensitivity}).\nA changepoint analysis (PELT~\\cite{killick2012optimal}) provides complementary, threshold-free evidence: exact agreement is 18/37 (49\\%; linear weighted $\\kappa{=}0.42$, moderate agreement), rising to 35/37 (95\\%) within $\\pm 1$; PELT is systematically conservative ($\\Kempirical_{\\text{PELT}} \\leq \\Kempirical_{\\text{OBD}}$ in all 19 disagreements; Appendix~\\ref{sec:changepoint_validation}).\nWe do not rely on changepoint agreement for $\\Kempirical$ determination.\n\n\\paragraph{Margin stratification.}\nTo assess the robustness of individual $\\Kempirical{=}2$ assignments, we stratify the seven continuation-mode configurations by their margin above $\\theta$ (CI lower $-$ $\\theta$; Table~\\ref{tab:kstar_ci_extended}).\nThree configurations across three families show confident margins exceeding 1\\,pp: Pythia-1.4B (4.5\\,pp), Qwen-base (1.7\\,pp), and Qwen-14B (1.2\\,pp).\nFour have marginal support (${<}\\,1$\\,pp): Qwen-7B (0.8\\,pp), OLMo-1B (0.5\\,pp), LLaMA-8B (0.3\\,pp), and Qwen-cont (0.2\\,pp); the last drops to $\\Kempirical{=}1$ under cross-scorer control (Section~\\ref{sec:transfer}).\nWe emphasize that $\\Kempirical$ is determined by bootstrap CI (Eq.~\\ref{eq:kstar}), not by permutation $p$-values, which serve as supplementary validation.\nThe $\\theta$-invariant domain ordering (Section~\\ref{sec:cross_domain}) is supported by the confident configurations alone and does not depend on marginal cases.\n\n%% ====================================================================\n\\subsection{Cross-Model Transfer and Its Limits}\n\\label{sec:transfer}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig3_transfer_heatmap.pdf}\n\\caption{Cross-model transfer heatmap. Each cell shows 6-class ordinal accuracy when trained on the row model and tested on the column model, divided by in-domain accuracy (retention rate). Pythia$\\leftrightarrow$OLMo: 90--92\\%; Qwen-rewrite$\\to$continuation: 61--63\\%.}\n\\label{fig:transfer_heatmap}\n\\end{figure}\n\nAggregate transfer is strong: continuation-mode classifiers retain 80--92\\% ordinal accuracy across generators at $\\leq$1.5B (Figure~\\ref{fig:transfer_heatmap}; Table~\\ref{tab:s1_transfer}), and 96--100\\% mean pairwise AUC at 7B (Appendix~\\ref{sec:7b_transfer}).\nHowever, boundary-level transfer is fragile: at 7B, 4/6 off-diagonal 1v2 pairs fall below $\\theta$, so $\\Kempirical{=}2$ assignments do not transfer at the boundary even as overall discriminability improves with scale.\nQwen-rewrite classifiers transfer poorly (61--63\\%), consistent with reliance on mode-specific artifacts.\n\n\\paragraph{Cross-scorer validation.}\nReplacing the self-scorer with Pythia-1.4B or OLMo-1B preserves feature rankings ($\\rho > 0.90$; Table~\\ref{tab:crossscorer}) and $\\Kempirical$ in 20/22 cross-scorer configurations on C4 and arXiv; the two exceptions are the most marginal boundary configurations (AUC within 0.002 of $\\theta$).\nNotably, the most marginal self-scored configuration (Qwen-cont, CI lower $= 0.602$, margin $0.2$\\,pp) drops to $\\Kempirical{=}1$ under Pythia and OLMo scoring (1v2 AUC $= 0.592$/$0.586$), reducing the continuation-mode count from 7/9 to 6/9 under strict cross-scorer control.\nFor arXiv, Pythia-1.4B cross-scoring preserves $\\Kempirical{=}3$ for 3/4 generators (2v3 $\\auc$: 0.608--0.632); Qwen-7B drops to borderline $\\Kempirical{=}2$ ($\\Delta = -2.7$\\,pp; Table~\\ref{tab:arxiv_crossscorer_ci}).\nA three-way ANOVA confirms Depth-Pair dominates variance ($\\eta^2_p = 0.998$; Scorer: $\\eta^2_p = 0.192$; Table~\\ref{tab:anova_crossscorer}); replacing the 1.5B scorer with Qwen2.5-7B preserves $\\Kempirical$ identically ($\\Delta\\,\\auc < 1$\\,pp; Appendix~\\ref{sec:scorer_scale}).\n\n%% ====================================================================\n\\subsection{Feature Ordering and Generation Mode}\n\\label{sec:feature_degradation}\n\\label{sec:generation_mode}\n\nAmong continuation-mode models, single-feature $\\auc$ rankings are highly correlated ($\\rho \\geq 0.85$; Table~\\ref{tab:top_features}), with the top-3 (\\texttt{surp\\_d1\\_std}, \\texttt{surp\\_std}, \\texttt{surp\\_d2\\_std}) shared across families; no single subset of size ${<}8$ sustains $\\Kempirical{=}2$ (Appendix~\\ref{sec:feature_subset}), and surprisal dominates on arXiv while C4 relies on feature combinations (Appendix~\\ref{sec:feature_ablation}).\nQwen-rewrite diverges ($\\Delta = +8.4$\\,pp), consistent with mode-specific artifacts; continuation mode is the canonical condition.\n\n%% ====================================================================\n\\subsection{Neural Probe}\n\\label{sec:neural_probe}\n\nA neural MLP probe on frozen encoder states (Table~\\ref{tab:neural_probe_crossmodel}) raises $K^*_{\\text{neural}}$ to 3 for Qwen (2v3 $\\auc = 0.616$) but not Pythia or OLMo ($\\auc_{2v3}$: 0.596, 0.589), reflecting self-familiarity artifacts; the 15D statistical features yield consistent $\\Kempirical = 2$ across all families.\n\n\\paragraph{Fine-tuned DeBERTa upper bound.}\nDeBERTa-v3-base ordinal classifiers raise 1v2 $\\auc$ over LightGBM at all three scales (1.5B: $0.705$ vs.\\ $0.626$; 14B: $0.678$ vs.\\ $0.621$; 32B: $0.694$ vs.\\ $0.618$) yet preserve $\\Kempirical{=}2$ (all 2v3 CI lower ${<}\\,\\theta$; Table~\\ref{tab:deberta_comparison}); LightGBM shifts by ${<}\\,0.5$\\,pp across 1.5B--32B.\nThe classifier gap reveals a feature-set-dependent two-tier structure: zero on C4 and Code (DeBERTa $\\Kempirical{=}2$, matching OBD), but $+2$ on Wikipedia (DeBERTa $\\Kempirical{=}3$; OLMo excluded) and $+1$ on arXiv (DeBERTa $\\Kempirical{=}4$, 3v4 $\\auc = 0.624$; Table~\\ref{tab:deberta_arxiv}); cross-transfer on Wikipedia mirrors the OBD pattern ($\\Kempirical{=}3$ drops to ${\\sim}2$; Table~\\ref{tab:wiki_deberta_transfer}).\nThe C4 result ($\\Kempirical_{\\text{DeBERTa}} = \\Kempirical_{\\text{OBD}} = 2$) establishes a representation-independent boundary: even a 184M-parameter fine-tuned encoder cannot surpass $\\Kempirical{=}2$ on web text.\nThe neural probe (Section~\\ref{sec:neural_probe}), which uses frozen encoder representations with a linear head, provides an intermediate reference point between 15D statistics and full DeBERTa fine-tuning.\n\n\\noindent\\begin{minipage}{\\columnwidth}\n\\centering\n\\footnotesize\n\\captionof{table}{DeBERTa-v3-base vs.\\ LightGBM on C4 generations at three scales. Both classifiers yield $\\Kempirical{=}2$ at 1.5B, 14B, and 32B.}\n\\label{tab:deberta_comparison}\n\\begin{tabular}{lccccc}\n\\toprule\n& \\textbf{0v1} & \\textbf{1v2} & \\textbf{2v3} & \\textbf{3v4} & \\textbf{4v5} \\\\\n\\midrule\nLightGBM (1.5B) & ---  & .626 & .549 & ---  & --- \\\\\nDeBERTa (1.5B)  & .992 & .705 & .599 & ---  & --- \\\\\n\\midrule\nLightGBM (14B)  & .960 & .621 & .549 & .524 & --- \\\\\nDeBERTa (14B)   & .994 & .678 & .590 & .565 & --- \\\\\n\\midrule\nLightGBM (32B)  & .958 & .618 & .545 & .522 & .516 \\\\\nDeBERTa (32B)   & .993 & .694 & .594 & .567 & .543 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{minipage}\n\n%% ====================================================================\n\\subsection{Cross-Domain Variation}\n\\label{sec:cross_domain}\n\nTo test whether $\\Kempirical$ reflects domain structure or model identity, we extend evaluation to arXiv ($n{=}2{,}200$), Wikipedia ($n{=}5{,}000$), and Code ($n{=}5{,}000$) across six configurations spanning four families (Table~\\ref{tab:domain_kstar}).\n\n\\paragraph{arXiv ($\\Kempirical{=}3$): five-model cross-validation.}\nAll five domain-competent models yield $\\Kempirical{=}3$ (2v3 $\\auc$: 0.6215--0.6545, all ${>}\\,\\theta$), reflecting formulaic features (LaTeX formatting, citation patterns) that degrade slowly and supply persistent depth signal across four families (1.4B--8B).\nRemoving LaTeX markup reduces 2v3 AUC by ${\\sim}$1.8\\,pp but preserves $\\Kempirical{=}3$ (CI lower $= 0.610$; Table~\\ref{tab:latex_ablation}).\nOLMo-1B is a capacity failure (0v1 JSD $= 0.33$), not a counter-example; Mistral-7B provides the strongest domain-dependence evidence ($\\Kempirical{=}1$ on C4 but $\\Kempirical{=}3$ on arXiv).\nThe arXiv subset ($n{=}2{,}200$ per depth) is smaller than C4 ($n{=}5{,}000$); at equal sample size, wider bootstrap CIs shift borderline C4 configurations below $\\theta$, yielding $\\Kempirical{=}1$; the $\\Kempirical{=}2$ verdict for these marginal C4 cases requires ${\\geq}5{,}000$ samples.\n\n\\paragraph{Wikipedia ($\\Kempirical{=}1$): single-generation saturation.}\nWith cross-family scorer control, all six models yield $\\Kempirical{=}1$ (1v2 $\\auc$: 0.498--0.595, all below $\\theta$): encyclopedic regularity provides minimal signal beyond the 0v1 boundary.\nSame-family scoring inflates Qwen to $\\Kempirical{=}2$ ($\\Delta = +2.4$\\,pp); cross-family scoring controls this bias (Appendix~\\ref{sec:wiki_domain}).\n\n\\paragraph{Code ($\\Kempirical{=}1$--$2$): cross-modality confirmation.}\nPython functions from CodeSearchNet~\\cite{husain2019codesearchnet} ($n{=}5{,}000$) yield $\\Kempirical{=}2$ for four models (1v2 $\\auc$: 0.615--0.739; Table~\\ref{tab:code_crossmodel_kstar}) with the same sharp 2v3 collapse as C4 (JSD ratio $11.7$--$13.5\\times$); Pythia-1.4B is capacity-limited ($\\Kempirical{=}1$, $\\auc = 0.598$; cross-family scorer: $\\Delta \\leq 1.9$\\,pp; Appendix~\\ref{sec:code_domain}).\n\n\\paragraph{Multi-source generator mixing.}\nMulti-source pooling (three generators per domain; Appendix~\\ref{sec:multi_source_details}) preserves domain-calibrated $\\Kempirical$ across all four domains (C4 $\\Kempirical{=}2$, unified 1v2 $\\auc = 0.711$, generator identity $+0.010$ mean $\\auc$ [range: $+0.001$, $+0.022$]; $\\Kempirical$ unchanged in all eight configurations; arXiv $\\Kempirical{=}3$; Code $\\Kempirical{=}2$; Wikipedia $\\Kempirical{=}1$), independently confirming the cross-scorer correction on Wikipedia.\n\n\\noindent\\begin{minipage}{\\columnwidth}\n\\centering\n\\footnotesize\n\\captionof{table}{Domain $\\times$ Model $\\Kempirical$ matrix (scorer-controlled). Wikipedia values use cross-family scorer (Pythia-1.4B). $^*$OLMo arXiv: capacity failure. $^\\dagger$Same-family scorer yields $\\Kempirical{=}2$; controlled value shown. $^\\ddagger$Borderline: Pythia CI upper $= 0.603$, Mistral CI lower $= 0.603$.}\n\\label{tab:domain_kstar}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & \\textbf{C4} & \\textbf{Code} & \\textbf{arXiv} & \\textbf{Wikipedia} \\\\\n\\midrule\nQwen-1.5B    & 2 & 2 & 3 & 1$^\\dagger$ \\\\\nQwen-7B      & 2 & 2 & 3 & 1$^\\dagger$ \\\\\nPythia-1.4B  & 2 & 1$^\\ddagger$ & 3 & 1 \\\\\nOLMo-1B      & 2 & --- & 1$^*$ & 1 \\\\\nGemma-2-2B   & 1 & --- & --- & --- \\\\\nLLaMA-3.1-8B & 2 & 2 & 3 & 1 \\\\\nMistral-7B   & 1 & 2$^\\ddagger$ & 3 & 1 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{minipage}\n\n\\paragraph{Summary.}\n\\label{sec:binary_confidence}\n$\\Kempirical{=}2$ at $\\theta{=}0.60$ for web text holds across four of six families (1B--14B), four decoding strategies, and multi-source pools (Gemma-2-2B and Mistral-7B: $\\Kempirical{=}1$; binary detectors: $K^*_{\\text{binary}} \\leq 1$, Table~\\ref{tab:s9_binary_spearman}).\nThe domain ordering arXiv $>$ C4 $=$ Code $>$ Wikipedia is $\\theta$-invariant; scale and architecture do not alter this ordering, confirming structural complexity as the primary determinant.\n",
      "numLines": 170,
      "startLine": 1,
      "totalLines": 170
    }
  },
  "sourceToolAssistantUUID": "a49c7d99-1bca-4f88-9dc8-f6f2cd084bc5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-21T06:34:50.276Z_

<details open><summary>🔧 Tool call — Read · `toolu_01E2XeVFiMmkNYLai8hV1oZJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c3.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4159c868-65f1-44e3-820c-816972f32d0e",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "bfde1167-24b6-446e-9f75-9ffb1f7f3cbf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 31 · 2026-05-21T06:34:50.282Z_

<details><summary>↩ Tool result · `toolu_01E2XeVFiMmkNYLai8hV1oZJ`</summary>

```text
1	\section{Consistency Check: $\Kempirical$-Guided Filtering}
2	\label{sec:filtering}
3	
4	\begin{table}[t]
5	\centering
6	\caption{Downstream evaluation after fine-tuning Qwen-2.5-1.5B on 30k C4 documents (depths 0--5), 3 seeds. Metrics: PIQA (acc\_norm), TruthfulQA (mc2), WinoGrande (acc), ARC-C (acc\_norm), GSM8K (exact match). Bold: best strategy.}
7	\label{tab:tab_filtering_main}
8	\resizebox{\columnwidth}{!}{\input{tables/tab_filtering_main}}
9	\end{table}
10	
11	The preceding sections establish $\Kempirical{=}2$ as a robust boundary; we test whether this predicts the correct curation strategy by fine-tuning Qwen-2.5-1.5B on 30{,}000 prompt-chain documents (depths 0--5; Table~\ref{tab:tab_filtering_main}).
12	Graduated filtering performs indistinguishably from no filtering ($\Delta \leq 0.53$\,pp across five benchmarks), confirming that depth weighting beyond $\Kempirical$ captures no signal; binary filtering selectively preserves mathematical reasoning (GSM8K $+$1.92\,pp) and factual accuracy (TruthfulQA $+$1.52\,pp) but degrades commonsense reasoning (WinoGrande $-$0.79\,pp).
13	All strategies incur capability cost relative to the base model; binary filtering partially mitigates this for reasoning tasks.
14	Effect sizes are small (max $+$1.92\,pp); these results demonstrate strategy ordering rather than absolute improvement.
15	Cross-model replication and rate sweeps (10--100\%) confirm graduated $\approx$ no-filter ordering (Appendix~\ref{sec:dose_response}, \ref{sec:pythia_filtering}, \ref{sec:rate_sweep}).
16	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bfde1167-24b6-446e-9f75-9ffb1f7f3cbf",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "6ec01cbb-0a43-46e8-94bd-f7b59824fd94",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c3.tex",
      "content": "\\section{Consistency Check: $\\Kempirical$-Guided Filtering}\n\\label{sec:filtering}\n\n\\begin{table}[t]\n\\centering\n\\caption{Downstream evaluation after fine-tuning Qwen-2.5-1.5B on 30k C4 documents (depths 0--5), 3 seeds. Metrics: PIQA (acc\\_norm), TruthfulQA (mc2), WinoGrande (acc), ARC-C (acc\\_norm), GSM8K (exact match). Bold: best strategy.}\n\\label{tab:tab_filtering_main}\n\\resizebox{\\columnwidth}{!}{\\input{tables/tab_filtering_main}}\n\\end{table}\n\nThe preceding sections establish $\\Kempirical{=}2$ as a robust boundary; we test whether this predicts the correct curation strategy by fine-tuning Qwen-2.5-1.5B on 30{,}000 prompt-chain documents (depths 0--5; Table~\\ref{tab:tab_filtering_main}).\nGraduated filtering performs indistinguishably from no filtering ($\\Delta \\leq 0.53$\\,pp across five benchmarks), confirming that depth weighting beyond $\\Kempirical$ captures no signal; binary filtering selectively preserves mathematical reasoning (GSM8K $+$1.92\\,pp) and factual accuracy (TruthfulQA $+$1.52\\,pp) but degrades commonsense reasoning (WinoGrande $-$0.79\\,pp).\nAll strategies incur capability cost relative to the base model; binary filtering partially mitigates this for reasoning tasks.\nEffect sizes are small (max $+$1.92\\,pp); these results demonstrate strategy ordering rather than absolute improvement.\nCross-model replication and rate sweeps (10--100\\%) confirm graduated $\\approx$ no-filter ordering (Appendix~\\ref{sec:dose_response}, \\ref{sec:pythia_filtering}, \\ref{sec:rate_sweep}).\n",
      "numLines": 16,
      "startLine": 1,
      "totalLines": 16
    }
  },
  "sourceToolAssistantUUID": "bfde1167-24b6-446e-9f75-9ffb1f7f3cbf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-21T06:34:50.747Z_

<details open><summary>🔧 Tool call — Read · `toolu_01YCEc3cGA2362JTsKQ8xEkr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6ec01cbb-0a43-46e8-94bd-f7b59824fd94",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "8be789b9-2930-4dbb-948b-c6b05d51f833",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 33 · 2026-05-21T06:34:50.752Z_

<details><summary>↩ Tool result · `toolu_01YCEc3cGA2362JTsKQ8xEkr`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	\label{sec:why_kstar}
4	\label{sec:one_wash}
5	\label{sec:negative_graduated}
6	\label{sec:repr_dependence}
7	\label{sec:boundary_cases}
8	\label{sec:length_confound}
9	
10	\begin{figure}[t]
11	\centering
12	\includegraphics[width=\columnwidth]{figures/fig_jsd_decay.pdf}
13	\caption{Token-level JSD between adjacent depth pairs on log scale. Blue band: min-max range across 7 continuation-mode C4 models (1B--14B) with $\Kempirical{=}2$; dashed purple: Mistral-7B ($\Kempirical{=}1$, cross-scorer validated); green: arXiv Pythia ($\Kempirical{=}3$); dotted red: retrain-chain ($\Kempirical{=}7$). C4 models exhibit a sharp cliff ($\lambda \approx 2.2$--$3.5$), while arXiv decays gradually ($\lambda \approx 1.0$) and retrain-chain shows no cliff ($\lambda = 0.285$).}
14	\label{fig:jsd_decay}
15	\end{figure}
16	
17	\paragraph{One-wash laundering (web text).}
18	For general web text, $\Kempirical{=}2$ at $\theta{=}0.60$ reflects concentrated information loss: starting from first-generation text ($\auc_{0v1} \geq 0.92$), a single additional generation pass renders text indistinguishable from deeper content (1v2 drops by ${\sim}$30\,pp; 2v3 falls below $\theta$).
19	
20	\paragraph{Operational value of the precise boundary.}
21	$\Kempirical{=}2$ resolves the question of filtering granularity: graduated weighting beyond depth~2 offers no advantage (Section~\ref{sec:filtering}), and the $\theta$-invariant domain ordering extends this across domains (Table~\ref{tab:deberta_arxiv}; rate sweeps in Appendix~\ref{sec:rate_sweep}).
22	
23	\paragraph{Prompt-chain vs.\ retrain-chain.}
24	All main results use prompt-chain ($\Kempirical{=}2$, text-intrinsic information loss).
25	Retrain-chain yields $\Kempirical{=}7$ (Appendix~\ref{sec:extended_limitations}), bounding the range; whether prompt-chain laundering masks retrain-chain signals remains open.
26	
27	\paragraph{JSD decay and domain dependence.}
28	Token-level JSD reveals two decay regimes (Figure~\ref{fig:jsd_decay}): C4 exhibits a sharp cliff ($\lambda \approx 2.9$), arXiv decays $3\times$ slower ($\lambda \approx 1.0$), and the retrain-chain shows no cliff ($\lambda = 0.285$; Appendix~\ref{sec:jsd_extended}).
29	Domain determines the $\Kempirical$ ordering; Wikipedia's template-driven structure causes single-generation saturation ($\Kempirical{=}1$; Table~\ref{tab:domain-ttr-entropy}).
30	
31	\paragraph{Feature-space ceiling and $\Kempirical_{\text{15D}}$ vs.\ $\Kempirical_{\text{intrinsic}}$.}
32	The domain ordering is \emph{feature-set invariant} (preserved under both 15D and DeBERTa), while absolute $\Kempirical$ values are \emph{feature-dependent}: DeBERTa extends $\Kempirical$ by $+2$ on Wikipedia and $+1$ on arXiv (Tables~\ref{tab:wiki_deberta_comparison}, \ref{tab:deberta_arxiv}), but matches the 15D bound on C4 and Code ($\Kempirical{=}2$), establishing a \emph{representation-independent boundary} (Table~\ref{tab:deberta_filtering}).
33	The progression 15D $\to$ neural probes ($K^*_{\text{neural}}{=}3$) $\to$ DeBERTa ($\Kempirical{=}4$) shows diminishing returns, suggesting $K^*_\text{theory} \approx 3$--$4$; permutation importance confirms saturation at 2v3 (Appendix~\ref{sec:feature_importance}).
34	
35	\paragraph{Multi-source pooling and transfer.}
36	Multi-source pooling preserves domain-calibrated $\Kempirical$ across all four domains, partially addressing the 4/6 off-diagonal boundary-level failure at 7B (Section~\ref{sec:transfer}): domain-calibrated ceilings hold under mixed-generator training even though $\Kempirical{=}2$ cannot be assumed when the generator is unknown.
37	
38	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8be789b9-2930-4dbb-948b-c6b05d51f833",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "bb33ecbc-757a-4bde-9393-86589a89c945",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\\label{sec:why_kstar}\n\\label{sec:one_wash}\n\\label{sec:negative_graduated}\n\\label{sec:repr_dependence}\n\\label{sec:boundary_cases}\n\\label{sec:length_confound}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_jsd_decay.pdf}\n\\caption{Token-level JSD between adjacent depth pairs on log scale. Blue band: min-max range across 7 continuation-mode C4 models (1B--14B) with $\\Kempirical{=}2$; dashed purple: Mistral-7B ($\\Kempirical{=}1$, cross-scorer validated); green: arXiv Pythia ($\\Kempirical{=}3$); dotted red: retrain-chain ($\\Kempirical{=}7$). C4 models exhibit a sharp cliff ($\\lambda \\approx 2.2$--$3.5$), while arXiv decays gradually ($\\lambda \\approx 1.0$) and retrain-chain shows no cliff ($\\lambda = 0.285$).}\n\\label{fig:jsd_decay}\n\\end{figure}\n\n\\paragraph{One-wash laundering (web text).}\nFor general web text, $\\Kempirical{=}2$ at $\\theta{=}0.60$ reflects concentrated information loss: starting from first-generation text ($\\auc_{0v1} \\geq 0.92$), a single additional generation pass renders text indistinguishable from deeper content (1v2 drops by ${\\sim}$30\\,pp; 2v3 falls below $\\theta$).\n\n\\paragraph{Operational value of the precise boundary.}\n$\\Kempirical{=}2$ resolves the question of filtering granularity: graduated weighting beyond depth~2 offers no advantage (Section~\\ref{sec:filtering}), and the $\\theta$-invariant domain ordering extends this across domains (Table~\\ref{tab:deberta_arxiv}; rate sweeps in Appendix~\\ref{sec:rate_sweep}).\n\n\\paragraph{Prompt-chain vs.\\ retrain-chain.}\nAll main results use prompt-chain ($\\Kempirical{=}2$, text-intrinsic information loss).\nRetrain-chain yields $\\Kempirical{=}7$ (Appendix~\\ref{sec:extended_limitations}), bounding the range; whether prompt-chain laundering masks retrain-chain signals remains open.\n\n\\paragraph{JSD decay and domain dependence.}\nToken-level JSD reveals two decay regimes (Figure~\\ref{fig:jsd_decay}): C4 exhibits a sharp cliff ($\\lambda \\approx 2.9$), arXiv decays $3\\times$ slower ($\\lambda \\approx 1.0$), and the retrain-chain shows no cliff ($\\lambda = 0.285$; Appendix~\\ref{sec:jsd_extended}).\nDomain determines the $\\Kempirical$ ordering; Wikipedia's template-driven structure causes single-generation saturation ($\\Kempirical{=}1$; Table~\\ref{tab:domain-ttr-entropy}).\n\n\\paragraph{Feature-space ceiling and $\\Kempirical_{\\text{15D}}$ vs.\\ $\\Kempirical_{\\text{intrinsic}}$.}\nThe domain ordering is \\emph{feature-set invariant} (preserved under both 15D and DeBERTa), while absolute $\\Kempirical$ values are \\emph{feature-dependent}: DeBERTa extends $\\Kempirical$ by $+2$ on Wikipedia and $+1$ on arXiv (Tables~\\ref{tab:wiki_deberta_comparison}, \\ref{tab:deberta_arxiv}), but matches the 15D bound on C4 and Code ($\\Kempirical{=}2$), establishing a \\emph{representation-independent boundary} (Table~\\ref{tab:deberta_filtering}).\nThe progression 15D $\\to$ neural probes ($K^*_{\\text{neural}}{=}3$) $\\to$ DeBERTa ($\\Kempirical{=}4$) shows diminishing returns, suggesting $K^*_\\text{theory} \\approx 3$--$4$; permutation importance confirms saturation at 2v3 (Appendix~\\ref{sec:feature_importance}).\n\n\\paragraph{Multi-source pooling and transfer.}\nMulti-source pooling preserves domain-calibrated $\\Kempirical$ across all four domains, partially addressing the 4/6 off-diagonal boundary-level failure at 7B (Section~\\ref{sec:transfer}): domain-calibrated ceilings hold under mixed-generator training even though $\\Kempirical{=}2$ cannot be assumed when the generator is unknown.\n\n",
      "numLines": 38,
      "startLine": 1,
      "totalLines": 38
    }
  },
  "sourceToolAssistantUUID": "8be789b9-2930-4dbb-948b-c6b05d51f833",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-21T06:34:51.219Z_

<details open><summary>🔧 Tool call — Read · `toolu_01TaH9n2nUkH14UAwohKJJzY`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bb33ecbc-757a-4bde-9393-86589a89c945",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "9a203892-bbf6-4526-acc8-54ef0121a370",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 35 · 2026-05-21T06:34:51.227Z_

<details><summary>↩ Tool result · `toolu_01TaH9n2nUkH14UAwohKJJzY`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We present the first empirical measurement of $\Kempirical$ across six architecture families, four domains, and four decoding strategies.
5	For web text, $\Kempirical{=}2$ holds across four of six families: a single generation pass renders text indistinguishable from deeper recursive content.
6	The $\theta$-invariant domain ordering arXiv ($\Kempirical{=}3$) $>$ C4 $=$ Code ($\Kempirical{=}2$) $>$ Wikipedia ($\Kempirical{=}1$) is feature-set invariant, with 15D features providing a conservative lower bound.
7	Leave-one-family-out cross-validation confirms that $\theta{=}0.60$ is robust across held-out families, and a non-Qwen derivation with Qwen validation rules out scorer overfitting.
8	For data curation, binary filtering at the $\Kempirical$ boundary suffices ($\Delta \leq 0.53$\,pp for graduated vs.\ no filtering); retrain-chain experiments extend the range to $\Kempirical \in [2, 7]$, with scaling beyond 14B and mixed chains remaining open.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9a203892-bbf6-4526-acc8-54ef0121a370",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "dcde7cf8-47d3-4133-8bfd-94723ce440bd",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe present the first empirical measurement of $\\Kempirical$ across six architecture families, four domains, and four decoding strategies.\nFor web text, $\\Kempirical{=}2$ holds across four of six families: a single generation pass renders text indistinguishable from deeper recursive content.\nThe $\\theta$-invariant domain ordering arXiv ($\\Kempirical{=}3$) $>$ C4 $=$ Code ($\\Kempirical{=}2$) $>$ Wikipedia ($\\Kempirical{=}1$) is feature-set invariant, with 15D features providing a conservative lower bound.\nLeave-one-family-out cross-validation confirms that $\\theta{=}0.60$ is robust across held-out families, and a non-Qwen derivation with Qwen validation rules out scorer overfitting.\nFor data curation, binary filtering at the $\\Kempirical$ boundary suffices ($\\Delta \\leq 0.53$\\,pp for graduated vs.\\ no filtering); retrain-chain experiments extend the range to $\\Kempirical \\in [2, 7]$, with scaling beyond 14B and mixed chains remaining open.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  },
  "sourceToolAssistantUUID": "9a203892-bbf6-4526-acc8-54ef0121a370",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-21T06:34:52.161Z_

<details open><summary>🔧 Tool call — Read · `toolu_017Sp724QybHWcsv6dijV24A`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dcde7cf8-47d3-4133-8bfd-94723ce440bd",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "339f316b-5f29-49a4-a246-50958af13b33",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 37 · 2026-05-21T06:34:52.314Z_

<details open><summary>🔧 Tool call — Read · `toolu_01K88WtKU97xUVTNqSgCZRkW`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "339f316b-5f29-49a4-a246-50958af13b33",
  "isSidechain": false,
  "requestId": "req_011CbFFQCeJGGWScy5swX6br",
  "type": "assistant",
  "uuid": "76357251-4f7d-4853-9c72-c5ad173193d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q4BbcuBnsMpjFtrjFsrSQ5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12263,
      "cache_read_input_tokens": 37801,
      "output_tokens": 794,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12263,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 794,
          "cache_read_input_tokens": 37801,
          "cache_creation_input_tokens": 12263,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12263
          },
          "type": "message"
        }
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

_source line 38 · 2026-05-21T06:34:52.411Z_

<details><summary>↩ Tool result · `toolu_017Sp724QybHWcsv6dijV24A`</summary>

```text
1	\appendix
2	\section{Notation}
3	\label{sec:notation}
4	
5	\begin{table}[htbp]
6	\centering
7	\small
8	\caption{Key symbols and abbreviations used throughout the paper.}
9	\label{tab:notation}
10	\resizebox{\columnwidth}{!}{%
11	\begin{tabular}{ll}
12	\toprule
13	\textbf{Symbol} & \textbf{Description} \\
14	\midrule
15	$\Kempirical$ & Empirical discrimination boundary (operational, feature-dependent) \\
16	$\Ktheory$ & Theoretical discrimination boundary (feature-independent upper limit) \\
17	$K^*_{\text{neural}}$ & $\Kempirical$ measured with neural probe (frozen encoder + MLP) \\
18	$K^*_{\text{binary}}$ & $\Kempirical$ of binary (human vs.\ machine) detectors \\
19	$\theta$ & AUC decision threshold (default 0.60) \\
20	$\auc$ & Area Under the ROC Curve (pairwise, between adjacent depths) \\
21	JSD & Jensen--Shannon Divergence (token-level, between adjacent depths) \\
22	OBD & Ordinal Binary Decomposition (classifier architecture) \\
23	LOFO & Leave-One-Family-Out cross-validation \\
24	PELT & Pruned Exact Linear Time changepoint detection \\
25	\bottomrule
26	\end{tabular}}
27	\end{table}
28	
29	\section{Supplementary Figures}
30	
31	\begin{figure}[htbp]
32	\centering
33	\includegraphics[width=\columnwidth]{figures/fig_filtering_strategies.pdf}
34	\caption{Downstream performance of all filtering strategies (5 seeds, $\pm$1 std). Binary-ours (green) minimizes MMLU degradation; graduated $\alpha$ sweep shows monotonic convergence toward binary. Dashed line: base model (no fine-tuning).}
35	\label{fig:filtering_strategies}
36	\end{figure}
37	
38	\begin{figure}[htbp]
39	  \centering
40	  \includegraphics[width=\columnwidth]{figures/fig_s1_auc_decay_ci.pdf}
41	  \caption{Pairwise $\auc$ decay curves for five model-mode configurations with bootstrap 95\% confidence intervals. Error bars computed from 1{,}000 bootstrap resamples. The shaded region marks the $\Kempirical=2$ boundary where $\auc$ drops below $\theta=0.60$. This figure complements Figure~\ref{fig:kstar_theta}(a) in the main text by showing statistical uncertainty for each measurement point.}
42	  \label{fig:s1_auc_decay_ci}
43	\end{figure}
44	
45	\FloatBarrier
46	\section{Supplementary Tables}
47	
48	%%% Feature ranking table (moved from main text)
49	\begin{table}[htbp]
50	\centering
51	\small
52	\caption{Top-3 features by single-feature $\auc$ ranking. Bold: shared across all continuation-mode models. Spearman $\rho$ (continuation pairs): Pythia--OLMo 0.95, Pythia--Qwen-cont 0.91, OLMo--Qwen-cont 0.85.}
53	\label{tab:top_features}
54	\resizebox{\columnwidth}{!}{%
55	\begin{tabular}{cllll}
56	\toprule
57	Rank & Pythia & OLMo & Qwen-rw & Qwen-cont \\
58	\midrule
59	1 & \textbf{\texttt{surp\_d1\_std}} & \textbf{\texttt{surp\_std}} & \texttt{freq\_entropy} & \textbf{\texttt{surp\_d1\_std}} \\
60	2 & \textbf{\texttt{surp\_d2\_std}} & \textbf{\texttt{surp\_d1\_std}} & \textbf{\texttt{surp\_std}} & \textbf{\texttt{surp\_std}} \\
61	3 & \textbf{\texttt{surp\_std}} & \textbf{\texttt{surp\_d2\_std}} & \textbf{\texttt{surp\_d1\_std}} & \textbf{\texttt{surp\_d2\_std}} \\
62	\bottomrule
63	\end{tabular}}
64	\end{table}
65	
66	%%% Table S1: Cross-Transfer Confusion Matrix (exp-013)
67	\begin{table*}[t]
68	  \centering
69	  \caption{Cross-model transfer accuracy matrix. Each cell reports the six-class depth classification accuracy of a detector trained on one model's outputs (row) and evaluated on another model's outputs (column). Diagonal entries (\textbf{bold}) indicate within-model performance. Transfer retention is computed as the ratio of off-diagonal accuracy to the geometric mean of the two corresponding diagonal entries.}
70	  \label{tab:s1_transfer}
71	  \begin{tabular}{lcccc}
72	    \toprule
73	    \multirow{2}{*}{\textbf{Train Model}} & \multicolumn{4}{c}{\textbf{Test Model}} \\
74	    \cmidrule(lr){2-5}
75	    & Qwen-rw & Pythia & OLMo & Qwen-cont \\
76	    \midrule
77	    Qwen-rw   & \textbf{0.4229} & 0.2590 & 0.2653 & 0.3466 \\
78	    Pythia    & 0.2718 & \textbf{0.3856} & 0.3531 & 0.3287 \\
79	    OLMo      & 0.2768 & 0.3450 & \textbf{0.3822} & 0.3244 \\
80	    Qwen-cont & 0.3440 & 0.3284 & 0.3112 & \textbf{0.3875} \\
81	    \bottomrule
82	  \end{tabular}
83	  \vspace{4pt}
84	
85	  \footnotesize
86	  \textit{Transfer retention} between models $A$ and $B$ is defined as $\frac{1}{2}\bigl(\frac{\mathrm{acc}(A \to B)}{\sqrt{\mathrm{acc}(A \to A) \cdot \mathrm{acc}(B \to B)}} + \frac{\mathrm{acc}(B \to A)}{\sqrt{\mathrm{acc}(A \to A) \cdot \mathrm{acc}(B \to B)}}\bigr)$.
87	  Notable pairs: Pythia$\leftrightarrow$OLMo 91--92\%, Qwen-cont$\leftrightarrow$Pythia 83--85\%, Qwen-cont$\leftrightarrow$OLMo 80--85\%, Qwen-rw$\to$Pythia/OLMo 61--63\%.
88	\end{table*}
89	
90	%%% Table S2: Decoding Ablation AUC (exp-003)
91	\begin{table*}[t]
92	  \centering
93	  \caption{Pairwise AUC with bootstrap 95\% CIs across depth pairs for four decoding configurations (all using Qwen2.5-1.5B-Instruct in rewrite mode; 10{,}000 bootstrap resamples). The horizontal rule between depth pairs 1\,vs.\,2 and 2\,vs.\,3 marks the empirical detectability boundary $\Kempirical=2$. Bottom rows report cross-configuration Spearman $\rho$ on per-feature discriminative-power rankings.}
94	  \label{tab:s2_decoding}
95	  \footnotesize
96	  \begin{tabular}{lcccc}
97	    \toprule
98	    \textbf{Depth Pair} & \textbf{Greedy} & \textbf{Nuc $p{=}0.9$, $T{=}1.0$} & \textbf{Nuc $p{=}0.95$, $T{=}0.7$} & \textbf{Nuc $p{=}0.95$, $T{=}1.2$} \\
99	    \midrule
100	    0 vs.\ 1 & $.980\;[.977,\,.982]$ & $.995\;[.993,\,.996]$ & $.988\;[.986,\,.990]$ & $.998\;[.998,\,.999]$ \\
101	    1 vs.\ 2 & $.689\;[.680,\,.698]$ & $.687\;[.677,\,.695]$ & $.689\;[.680,\,.697]$ & $.704\;[.695,\,.713]$ \\
102	    \cmidrule(lr){1-5}
103	    2 vs.\ 3 & $.561\;[.552,\,.571]$ & $.592\;[.582,\,.601]$\rlap{$^\dagger$} & $.590\;[.581,\,.600]$ & $.582\;[.572,\,.592]$ \\
104	    3 vs.\ 4 & $.540\;[.531,\,.550]$ & $.547\;[.537,\,.557]$ & $.539\;[.529,\,.549]$ & $.529\;[.519,\,.540]$ \\
105	    4 vs.\ 5 & $.514\;[.503,\,.524]$ & $.507\;[.496,\,.517]^{\ddagger}$ & $.535\;[.524,\,.545]$ & $.524\;[.513,\,.535]$ \\
106	    \midrule
107	    \multicolumn{5}{l}{\textbf{Cross-config feature Spearman $\rho$}} \\
108	    \midrule
109	    \multicolumn{2}{l}{Greedy vs.\ Nuc $p{=}0.9$} & 0.600 &
110	    \multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\ $T{=}0.7$} & 0.782 \\
111	    \multicolumn{2}{l}{Greedy vs.\ $T{=}0.7$} & 0.914 &
112	    \multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\ $T{=}1.2$} & 0.893 \\
113	    \multicolumn{2}{l}{Greedy vs.\ $T{=}1.2$} & 0.532 &
114	    \multicolumn{1}{l}{$T{=}0.7$ vs.\ $T{=}1.2$} & 0.668 \\
115	    \bottomrule
116	    \multicolumn{5}{l}{${}^{\dagger}$\,CI upper bound (0.601) marginally exceeds $\theta{=}0.60$ by 0.001.} \\
117	    \multicolumn{5}{l}{${}^{\ddagger}$\,Permutation $p = 0.12$ (not significant). All other pairs $p < 0.01$.}
118	  \end{tabular}
119	\end{table*}
120	
121	%%% Table S2b: Extended K* CI (all models including new additions)
122	\begin{table*}[t]
123	  \centering
124	  \footnotesize
125	  \caption{Extended pairwise $\auc$ with bootstrap 95\% CIs for 9 C4 configurations (Gemma-2-2B reported in Table~\ref{tab:domain_kstar}).
126	  This table extends Table~\ref{tab:kstar_ci} in the main text with Qwen-base, Qwen-14B, LLaMA-8B, and Mistral-7B.
127	  7/9 continuation-mode configurations yield $\Kempirical = 2$; Mistral-7B yields $\Kempirical = 1$; Qwen-rw$^\dagger$ is rewrite mode (ablation).}
128	  \label{tab:kstar_ci_extended}
129	  \resizebox{\textwidth}{!}{%
130	  \begin{tabular}{lcccccccccccccccccc}
131	    \toprule
132	     & \multicolumn{2}{c}{Qwen-rw\rlap{$^\dagger$}} & \multicolumn{2}{c}{Pythia} & \multicolumn{2}{c}{OLMo} & \multicolumn{2}{c}{Qwen-cont} & \multicolumn{2}{c}{Qwen-7B\rlap{$^\ddagger$}} & \multicolumn{2}{c}{Qwen-14B\rlap{$^\ddagger$}} & \multicolumn{2}{c}{Qwen-base} & \multicolumn{2}{c}{LLaMA-8B} & \multicolumn{2}{c}{Mistral-7B} \\
133	    \cmidrule(lr){2-3}\cmidrule(lr){4-5}\cmidrule(lr){6-7}\cmidrule(lr){8-9}\cmidrule(lr){10-11}\cmidrule(lr){12-13}\cmidrule(lr){14-15}\cmidrule(lr){16-17}\cmidrule(lr){18-19}
134	     & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI \\
135	    \midrule
136	    0v1 & .9956 & & .9932 & & .9970 & & .9971 & & .9638 & [.961,\,.967] & .960 & [.956,\,.963] & .987 & [.985,\,.989] & .9225 & [.918,\,.927] & .930 & [.925,\,.935] \\
137	    1v2 & .6955 & [.686,\,.704]\rlap{$^*$} & .6539 & [.645,\,.663]\rlap{$^*$} & .6145 & [.605,\,.625]\rlap{$^*$} & .6112 & [.602,\,.621]\rlap{$^*$} & .6168 & [.608,\,.626]\rlap{$^*$} & .621 & [.612,\,.630]\rlap{$^*$} & .626 & [.617,\,.635]\rlap{$^*$} & .6123 & [.603,\,.622]\rlap{$^*$} & .594 & [.584,\,.603] \\
138	    2v3 & .5893 & [.580,\,.599] & .5514 & [.542,\,.563] & .5496 & [.540,\,.560] & .5609 & [.551,\,.571] & .5492 & [.539,\,.559] & .549 & [.539,\,.559] & .550 & [.540,\,.560] & .5518 & [.542,\,.562] & .548 & [.538,\,.558] \\
139	    3v4 & .5435 & & .5152 & & .5091 & & .5409 & & .5276 & & .524 & [.514,\,.535] & .529 & [.519,\,.540] & .5203 & [.510,\,.531] & .521 & \\
140	    4v5 & .5340 & & .5136 & & .5045 & & .5141 & & .5085 & & .515 & [.505,\,.527] & .518 & [.508,\,.529] & .5089 & [.499,\,.519] & .510 & \\
141	    \bottomrule
142	    \multicolumn{19}{l}{\footnotesize $^*$Permutation $p < 0.001$ for all boundary comparisons. Mistral-7B 1v2: $p = 0.001$ but $\auc < \theta$, hence $\Kempirical{=}1$.} \\
143	    \multicolumn{19}{l}{\footnotesize $^\dagger$Rewrite mode (ablation); excluded from continuation-mode $\Kempirical$ claim.} \\
144	    \multicolumn{19}{l}{\footnotesize $^\ddagger$Qwen-7B: Qwen2.5-7B (fp16); Qwen-14B: Qwen2.5-14B; scorer: Qwen2.5-1.5B.}
145	  \end{tabular}}
146	
147	\end{table*}
148	
149	%%% Table S3: LLM Zero-Shot Confusion Matrices (exp-011)
150	\begin{table*}[t]
151	  \centering
152	  \caption{LLM zero-shot depth classification: $5{\times}5$ confusion matrices
153	    (Exp-011). Both frontier LLMs achieve high binary detection accuracy
154	    (GPT-5.5: 0.8780; Claude Opus~4.6: 0.8818) but near-chance 5-class
155	    accuracy (${\sim}0.33$ vs.\ OBD-LightGBM baseline 0.386, evaluated on the full test set $N{=}5{,}000$). GPT-5.5
156	    strongly identifies depth-0 text (recall${=}0.7700$) but collapses on
157	    depth-4 (recall${=}0.0800$), misclassifying 50/100 depth-4 samples as
158	    depth-2. Claude Opus~4.6 shows more uniform errors across depths 1--4,
159	    with depth-4 recall (0.3700) substantially exceeding GPT-5.5.
160	    Per-depth recall comparison with OBD-LightGBM in Table~\ref{tab:s3c_perdepth}.}
161	  \label{tab:s3_llm_zeroshot}
162	
163	  \vspace{0.5em}
164	  \begin{subtable}{0.48\textwidth}
165	    \centering
166	    \caption{GPT-5.5 ($N{=}500$, acc${=}0.332$, MAE${=}1.102$)}
167	    \label{tab:s3a_gpt55}
168	    \small
169	    \begin{tabular}{lcccccc}
170	      \toprule
171	      & \multicolumn{5}{c}{Predicted Depth} & \\
172	      \cmidrule(lr){2-6}
173	      True & 0 & 1 & 2 & 3 & 4 & Rec. \\
174	      \midrule
175	      0 & \textbf{77} & 18 &  4 &  0 &  1 & .770 \\
176	      1 &  9 & \textbf{19} & 36 & 24 & 12 & .190 \\
177	      2 &  8 & 10 & \textbf{38} & 35 &  9 & .380 \\
178	      3 & 10 & 16 & 35 & \textbf{24} & 15 & .240 \\
179	      4 & 11 & 13 & 50 & 18 &  \textbf{8} & .080 \\
180	      \bottomrule
181	    \end{tabular}
182	  \end{subtable}
183	  \hfill
184	  \begin{subtable}{0.48\textwidth}
185	    \centering
186	    \caption{Claude Opus~4.6 ($N{=}499$, acc${=}0.331$, MAE${=}1.150$)}
187	    \label{tab:s3b_claude}
188	    \small
189	    \begin{tabular}{lcccccc}
190	      \toprule
191	      & \multicolumn{5}{c}{Predicted Depth} & \\
192	      \cmidrule(lr){2-6}
193	      True & 0 & 1 & 2 & 3 & 4 & Rec. \\
194	      \midrule
195	      0 & \textbf{69} & 26 &  3 &  0 &  2 & .690 \\
196	      1 &  8 & \textbf{21} & 32 & 11 & 28 & .210 \\
197	      2 &  6 & 36 & \textbf{28} &  5 & 25 & .280 \\
198	      3 &  7 & 20 & 31 & \textbf{10} & 31 & .100 \\
199	      4 &  7 & 28 & 22 &  6 & \textbf{37} & .370 \\
200	      \bottomrule
201	    \end{tabular}
202	  \end{subtable}
203	\end{table*}
204	
205	\begin{table}[htbp]
206	  \centering
207	  \small
208	  \caption{Per-depth recall (\%) on balanced $N{=}500$ test set. OBD's nominal overall accuracy gap originates from depth-0; all methods fail at depths $\geq 2$, consistent with $\Kempirical = 2$.}
209	  \label{tab:s3c_perdepth}
210	  \resizebox{\columnwidth}{!}{%
211	  \begin{tabular}{lccccc}
212	    \toprule
213	    & Depth 0 & Depth 1 & Depth 2 & Depth 3 & Depth 4 \\
214	    \midrule
215	    OBD-LightGBM & \textbf{96} & \textbf{39} & 14 & 19 & 22 \\
216	    GPT-5.5      & 77 & 19 & \textbf{38} & \textbf{24} &  8 \\
217	    Claude Opus~4.6 & 69 & 21 & 28 & 10 & \textbf{37} \\
218	    \bottomrule
219	  \end{tabular}}
220	\end{table}
221	
222	\paragraph{Zero-shot prompt template.}
223	Both GPT-5.5 and Claude Opus~4.6 received the following system prompt (temperature 0, single-token output constraint):
224	
225	\begin{quote}
226	\small
227	\texttt{The following text passage was produced through recursive LLM generation starting from human-written text (depth~0). Each successive generation feeds the previous output back to the LLM: depth~0 = human, depth~1 = first LLM pass, depth~2 = second pass, etc.}
228	
229	\texttt{Estimate the generational depth (0, 1, 2, 3, or 4) of the passage below. Respond with only the depth number.}
230	
231	\texttt{Text: \{text\}}
232	\end{quote}
233	
234	%%% Table: Token Length and EOS Truncation Analysis
235	\begin{table*}[t]
236	  \centering
237	  \small
238	  \caption{Mean subword token count per depth and EOS truncation rate (\%) for depth~1+ across all model configurations (generation limit: 256 tokens). Depth~0 (human text) is shared across configurations. Depths 1--5 show no systematic length trend within any model; the 0v1 length asymmetry (human texts shorter) makes detection \emph{more conservative}, not inflated. See Section~\ref{sec:length_confound} for discussion.}
239	  \label{tab:token_length}
240	  \begin{tabular}{lcccccccc}
241	    \toprule
242	    & \multicolumn{6}{c}{\textbf{Mean Token Count}} & & \\
243	    \cmidrule(lr){2-7}
244	    \textbf{Model} & Depth 0 & Depth 1 & Depth 2 & Depth 3 & Depth 4 & Depth 5 & \textbf{EOS Trunc.\ (\%)} & \textbf{Severity} \\
245	    \midrule
246	    Qwen-rw (1.5B)  & 191 & 254 & 252 & 254 & 254 & 254 & 7--11 & Mild \\
247	    Pythia-1.4B      & 192 & 214 & 215 & 216 & 217 & 218 & 34--36 & High \\
248	    OLMo-1B          & 192 & 256 & 256 & 256 & 256 & 256 & $<$1 & Negligible \\
249	    Qwen-cont (1.5B) & 191 & 244 & 238 & 240 & 240 & 238 & 17--20 & Moderate \\
250	    Qwen-7B          & 191 & 196 & 195 & 193 & 197 & 197 & 45--47 & High \\
251	    \midrule
252	    \multicolumn{9}{l}{\textit{Decoding ablation (Qwen-rw 1.5B)}} \\
253	    \quad Greedy          & 191 & 253 & 252 & 253 & 254 & 254 & 8--12 & Mild \\
254	    \quad Nuc $p{=}0.9$   & 191 & 254 & 251 & 254 & 253 & 254 & 8--16 & Mild \\
255	    \quad $T{=}0.7$       & 191 & 253 & 251 & 253 & 253 & 254 & 8--14 & Mild \\
256	    \quad $T{=}1.2$       & 191 & 254 & 252 & 253 & 254 & 254 & 8--16 & Mild \\
257	    \bottomrule
258	  \end{tabular}
259	
260	  \vspace{4pt}
261	  \footnotesize
262	  EOS truncation rate: percentage of depth~1+ samples where generation terminated via EOS before reaching the 256-token limit. Ranges span depths 1--5.
263	\end{table*}
264	
265	%%% Table S4: Dataset Statistics
266	\begin{table}[htbp]
267	  \centering
268	  \small
269	  \caption{Dataset statistics for the generational depth corpus. Depth~0 contains human-written seed texts sampled from the C4 English validation split and truncated to 256 subword tokens. Depths~1--5 are recursively generated by Qwen2.5-1.5B-Instruct (nucleus sampling, $p{=}0.95$, $T{=}1.0$). Token counts use whitespace tokenization. Statistics shown for the primary Qwen-rewrite corpus; the other three model-mode configurations (Pythia-cont, OLMo-cont, Qwen-cont) share the same generation pipeline and corpus structure.}
270	  \label{tab:s4_dataset_stats}
271	  \resizebox{\columnwidth}{!}{%
272	  \begin{tabular}{clrl}
273	    \toprule
274	    \textbf{Depth} & \textbf{$N$ samples} & \textbf{Mean tokens} & \textbf{Source} \\
275	    \midrule
276	    0 & 5{,}000 & 147.8 & C4 validation (human) \\
277	    1 & 5{,}000 & 207.1 & Qwen2.5-1.5B rewrite \\
278	    2 & 5{,}000 & 206.1 & Qwen2.5-1.5B rewrite \\
279	    3 & 5{,}000 & 208.0 & Qwen2.5-1.5B rewrite \\
280	    4 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\
281	    5 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\
282	    \midrule
283	    \multicolumn{2}{l}{Total} & \multicolumn{2}{l}{30{,}000 samples} \\
284	    \bottomrule
285	  \end{tabular}}
286	\end{table}
287	
288	%%% Table S5: Complete 15-D Feature Descriptions
289	\begin{table*}[t]
290	  \centering
291	  \caption{Complete description of the 15-dimensional feature set used by the OBD classifier. Features are grouped into three families: surprisal statistics (9~dims) computed from Qwen2.5-1.5B token-level log-probabilities, lexical diversity (3~dims), and frequency tail shape (3~dims). All features are computed per document.}
292	  \label{tab:s5_features}
293	  \begin{tabular}{llp{0.45\textwidth}l}
294	    \toprule
295	    \textbf{Group} & \textbf{Feature} & \textbf{Description} & \textbf{Range} \\
296	    \midrule
297	    \multirow{9}{*}{\rotatebox[origin=c]{90}{\textsc{Surprisal}}}
298	    & \texttt{surp\_mean}   & Mean token surprisal $\frac{1}{T}\sum_t -\log p(x_t \mid x_{&lt;t})$ & $\mathbb{R}^+$ \\
299	    & \texttt{surp\_std}    & Standard deviation of token surprisal & $\mathbb{R}^+$ \\
300	    & \texttt{surp\_skew}   & Skewness of the surprisal distribution & $\mathbb{R}$ \\
301	    & \texttt{surp\_kurt}   & Excess kurtosis of the surprisal distribution & $\mathbb{R}$ \\
302	    & \texttt{surp\_d1\_mean} & Mean of first-order surprisal differences $\Delta s_t = s_{t+1} - s_t$ & $\mathbb{R}$ \\
303	    & \texttt{surp\_d1\_std}  & Std of first-order surprisal differences & $\mathbb{R}^+$ \\
304	    & \texttt{surp\_d1\_skew} & Skewness of first-order surprisal differences & $\mathbb{R}$ \\
305	    & \texttt{surp\_d2\_mean} & Mean of second-order differences $\Delta^2 s_t$ & $\mathbb{R}$ \\
306	    & \texttt{surp\_d2\_std}  & Std of second-order surprisal differences & $\mathbb{R}^+$ \\
307	    \midrule
308	    \multirow{3}{*}{\rotatebox[origin=c]{90}{\textsc{Lex}}}
309	    & \texttt{ttr}          & Type-token ratio: $|V| / T$ & $[0, 1]$ \\
310	    & \texttt{hapax\_ratio} & Hapax legomena ratio: freq-1 types / unique types & $[0, 1]$ \\
311	    & \texttt{self\_bleu}   & Mean 4-gram BLEU against 100 random same-depth samples & $[0, 1]$ \\
312	    \midrule
313	    \multirow{3}{*}{\rotatebox[origin=c]{90}{\textsc{Freq}}}
314	    & \texttt{freq\_kurtosis}  & Excess kurtosis of word frequency distribution & $\mathbb{R}$ \\
315	    & \texttt{freq\_entropy}   & Shannon entropy of word frequencies: $-\sum p_w \log_2 p_w$ & $\mathbb{R}^+$ \\
316	    & \texttt{low\_freq\_ratio} & Proportion of vocabulary with count $\leq 2$ & $[0, 1]$ \\
317	    \bottomrule
318	  \end{tabular}
319	\end{table*}
320	
321	%%% Tables S6 & S7: Side by side in a single table* to avoid table*/table overlap
322	\begin{table*}[t]
323	\begin{minipage}[t]{0.45\textwidth}
324	  \centering
325	  \small
326	  \captionof{table}{LightGBM hyperparameters for the pairwise OBD (Ordinal Binary Decomposition) classifier used throughout the paper. One binary classifier is trained per adjacent depth pair $(k, k{+}1)$; 5-fold GroupKFold cross-validation is grouped by \texttt{doc\_id} to prevent data leakage from the same seed document appearing in both train and test.}
327	  \label{tab:s6_lgbm_params}
328	  \begin{tabular}{ll}
329	    \toprule
330	    \textbf{Parameter} & \textbf{Value} \\
331	    \midrule
332	    \texttt{n\_estimators}      & 200 \\
333	    \texttt{learning\_rate}     & 0.05 \\
334	    \texttt{max\_depth}         & 6 \\
335	    \texttt{num\_leaves}        & 31 \\
336	    \texttt{verbose}            & $-1$ \\
337	    \texttt{n\_jobs}            & $-1$ (all cores) \\
338	    Cross-validation            & 5-fold GroupKFold \\
339	    Grouping key                & \texttt{doc\_id} \\
340	    Objective                   & Binary (per depth pair) \\
341	    \bottomrule
342	  \end{tabular}
343	\end{minipage}\hfill
344	\begin{minipage}[t]{0.52\textwidth}
345	  \centering
346	  \small
347	  \captionof{table}{Neural probe architecture and training details (Exp-015). Applied to all three model families (Qwen2.5-1.5B, Pythia-1.4B, OLMo-1B): each model's frozen hidden states are average-pooled into document embeddings and classified by a two-hidden-layer MLP.}
348	  \label{tab:s7_neural_probe}
349	  \resizebox{\textwidth}{!}{%
350	  \begin{tabular}{ll}
351	    \toprule
352	    \textbf{Component} & \textbf{Details} \\
353	    \midrule
354	    \multicolumn{2}{l}{\textit{Embedding extraction}} \\
355	    Base models       & Qwen2.5-1.5B / Pythia-1.4B / OLMo-1B (frozen) \\
356	    Representation    & Last hidden state, attention-masked avg pool \\
357	    Embedding dim     & 1536 / 2048 / 2048 \\
358	    Max sequence len   & 512 tokens \\
359	    \midrule
360	    \multicolumn{2}{l}{\textit{MLP classifier}} \\
361	    Architecture      & $d_{\text{emb}} \to 512 \to 256 \to 6$ \\
362	    Activations       & ReLU \\
363	    Dropout           & 0.1 (after each hidden layer) \\
364	    Output            & 6-class softmax \\
365	    \midrule
366	    \multicolumn{2}{l}{\textit{Training}} \\
367	    Optimizer         & Adam ($\text{lr} = 10^{-3}$, weight decay $= 10^{-4}$) \\
368	    Loss              & Cross-entropy \\
369	    Batch size        & 256 \\
370	    Max epochs        & 20 \\
371	    Early stopping    & Patience = 5 (validation loss) \\
372	    Cross-validation  & 5-fold GroupKFold \\
373	    \bottomrule
374	  \end{tabular}%
375	  }
376	\end{minipage}
377	\end{table*}
378	
379	%%% Table S9: Binary Detector Spearman ρ (exp-012)
380	\begin{table*}[t]
381	  \centering
382	  \small
383	  \caption{Spearman rank correlation ($\rho$) between binary detector confidence scores and true generational depth, and 6-class depth classification accuracy (Exp-012). Three metrics: log-PPL from the reference model (DivEye), log-PPL from the observer model, and PPL ratio (Binoculars; observer: Pythia-1.4B, performer: OLMo-1B). Random baseline for 6-class accuracy: 0.167. While statistically significant, correlations are driven by the 0v1 boundary; confidence scores do not monotonically track depth beyond generation~1. Qwen-rewrite exhibits reversed sign ($\rho > 0$), indicating that generation mode alters the direction of binary confidence's relationship with depth.}
384	  \label{tab:s9_binary_spearman}
385	  \begin{tabular}{lcccc}
386	    \toprule
387	    & \textbf{Qwen-rw} & \textbf{Pythia} & \textbf{OLMo} & \textbf{Qwen-cont} \\
388	    \midrule
389	    \multicolumn{5}{l}{\textit{Spearman $\rho$ with true depth}} \\
390	    \quad log-PPL (ref)      & $-0.123$ & $-0.297$ & $-0.378$ & $-0.389$ \\
391	    \quad log-PPL (observer) & $+0.082$ & $-0.453$ & $-0.461$ & $-0.162$ \\
392	    \quad PPL ratio           & $+0.119$ & $-0.392$ & $-0.407$ & $-0.058$ \\
393	    \midrule
394	    \multicolumn{5}{l}{\textit{Classification}} \\
395	    \quad 6-class accuracy    & 0.199    & 0.130    & 0.127    & 0.183 \\
396	    \midrule
397	    \multicolumn{5}{l}{Random baseline: 0.167 \quad $K^*_{\text{binary}} = 1$ \quad $K^*_{\text{OBD}} = 2$} \\
398	    \bottomrule
399	  \end{tabular}
400	\end{table*}
401	
402	%%% Table S10: Pythia Decoding Ablation (exp-020)
403	\begin{table*}[t]
404	  \centering
405	  \small
406	  \caption{Pairwise $\auc$ with bootstrap 95\% CIs across depth pairs for Pythia-1.4B under four decoding configurations (Exp-020; 10{,}000 bootstrap resamples). Complements Table~\ref{tab:s2_decoding} (Qwen-rewrite) with a second model family. $^\dagger$Greedy decoding triggers repetition collapse in Pythia-1.4B (4-gram repeat rate: $d_0{=}0.01 \to d_1{=}0.72$), inflating 0v1 and 1v2 AUC via lexical degeneracy rather than depth-discriminative features.}
407	  \label{tab:s10_pythia_decoding}
408	  \begin{tabular}{lcccc}
409	    \toprule
410	    \textbf{Depth Pair} & \textbf{Greedy}$^\dagger$ & \textbf{Nuc $p{=}0.9$, $T{=}1.0$} & \textbf{Nuc $p{=}0.95$, $T{=}0.7$} & \textbf{Nuc $p{=}0.95$, $T{=}1.2$} \\
411	    \midrule
412	    0 vs.\ 1 & .9992 & .9948 & .9965 & .9933 \\
413	    1 vs.\ 2 & .8838 & .6770 & .7265 & .6172 \\
414	    \cmidrule(lr){1-5}
415	    2 vs.\ 3 & .5342 & .5549 & .5941 & .5226 \\
416	    3 vs.\ 4 & .5228 & .5299 & .5698 & .5170 \\
417	    4 vs.\ 5 & .5162 & .5013 & .5284 & .5051 \\
418	    \midrule
419	    $\Kempirical$ & 2 & 2 & 2 & 2 \\
420	    \bottomrule
421	  \end{tabular}
422	\end{table*}
423	
424	%%% Table S11: Length Ablation (exp-021)
425	\begin{table*}[t]
426	  \centering
427	  \small
428	  \caption{Pairwise $\auc$ across depth pairs for three segment lengths (Exp-021; Qwen2.5-1.5B base, continuation mode). $\Kempirical{=}2$ is confirmed for 128 and 256 tokens; 512 tokens yields point estimate $\Kempirical{=}2$ but the 1v2 bootstrap CI lower bound falls marginally below $\theta$.}
429	  \label{tab:s11_length_ablation}
430	  \begin{tabular}{lccc}
431	    \toprule
432	    \textbf{Depth Pair} & \textbf{128 tokens} & \textbf{256 tokens} & \textbf{512 tokens} \\
433	    \midrule
434	    0 vs.\ 1 & .9948 & .9956 & .9961 \\
435	    1 vs.\ 2 & .6219 & .6282 & .6073$^\dagger$ \\
436	    \cmidrule(lr){1-4}
437	    2 vs.\ 3 & .5531 & .5609 & .5482 \\
438	    3 vs.\ 4 & .5218 & .5305 & .5196 \\
439	    4 vs.\ 5 & .5104 & .5142 & .5078 \\
440	    \midrule
441	    $\Kempirical$ & 2 & 2 & 2$^\dagger$ \\
442	    \bottomrule
443	    \multicolumn{4}{l}{\footnotesize $^\dagger$CI $[0.5979,\,0.6166]$; lower bound ${<}\theta{=}0.60$.}
444	  \end{tabular}
445	\end{table*}
446	
447	%%% Table S12: Domain Ablation
448	\begin{table*}[t]
449	  \centering
450	  \small
451	  \caption{Pairwise $\auc$ across depth pairs for three text domains (Qwen2.5-1.5B base, continuation mode). Tests generalization of $\Kempirical{=}2$ beyond C4 web text to structured and technical domains. Same-family scoring (Qwen-1.5B); cross-family controlled values in Table~\ref{tab:wiki_domain}.}
452	  \label{tab:s12_domain_ablation}
453	  \begin{tabular}{lccc}
454	    \toprule
455	    \textbf{Depth Pair} & \textbf{C4 (web)} & \textbf{Wikipedia} & \textbf{arXiv} \\
456	    \midrule
457	    0 vs.\ 1 & .9971 & .996 & .9984 \\
458	    1 vs.\ 2 & .6112 & .6193 & .8580 \\
459	    \cmidrule(lr){1-4}
460	    2 vs.\ 3 & .5609 & .556 & .6427 \\
461	    3 vs.\ 4 & .5409 & .528 & .5813 \\
462	    4 vs.\ 5 & .5141 & .509 & .5346 \\
463	    \midrule
464	    $\Kempirical$ & 2 & 2 & 3 \\
465	    \bottomrule
466	  \end{tabular}
467	\end{table*}
468	
469	%%% Table S13: Scorer Sensitivity Analysis
470	\begin{table*}[t]
471	  \centering
472	  \small
473	  \caption{Scorer sensitivity: $\Kempirical$ under self-scoring vs.\ cross-scoring. Self-scorer uses the generator's own model family for feature extraction; cross-scorer uses alternative models (Pythia-1.4B, OLMo-1B). $\Kempirical$ agreement across scorer conditions indicates the boundary is governed by the generation process. Cross-scoring reduces $\Kempirical$ only for the most marginal self-scorer condition (Qwen-continuation).}
474	  \label{tab:s13_scorer_sensitivity}
475	  \begin{tabular}{lccccc}
476	    \toprule
477	    & & \multicolumn{3}{c}{\textbf{Scorer}} & \\
478	    \cmidrule(lr){3-5}
479	    \textbf{Generator} & \textbf{Mode} & \textbf{Self} & \textbf{Pythia} & \textbf{OLMo} & \textbf{Agreement} \\
480	    \midrule
481	    Qwen-1.5B-Instruct & Rewrite      & 2 (.696) & 2 & 2 & \checkmark \\
482	    Qwen-1.5B-Instruct & Continuation & 2 (.611) & 1 & 1 & $\times$ \\
483	    Qwen-1.5B (base)   & Continuation & 2 (.626) & 2 & 2 & \checkmark \\
484	    Pythia-1.4B         & Continuation & 2 (.654) & 2 & 2 & \checkmark \\
485	    OLMo-1B             & Continuation & 2 (.615) & 2 & 2 & \checkmark \\
486	    Qwen-7B             & Continuation & 2 (.618) & 2 & 2 & \checkmark \\
487	    Mistral-7B          & Continuation & 1 (.594) & 1 & 1 & \checkmark \\
488	    \bottomrule
489	  \end{tabular}
490	\end{table*}
491	
492	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "339f316b-5f29-49a4-a246-50958af13b33",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "7226b6af-0ed4-40b9-8ac1-d70c399176c1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex",
      "content": "\\appendix\n\\section{Notation}\n\\label{sec:notation}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Key symbols and abbreviations used throughout the paper.}\n\\label{tab:notation}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Symbol} & \\textbf{Description} \\\\\n\\midrule\n$\\Kempirical$ & Empirical discrimination boundary (operational, feature-dependent) \\\\\n$\\Ktheory$ & Theoretical discrimination boundary (feature-independent upper limit) \\\\\n$K^*_{\\text{neural}}$ & $\\Kempirical$ measured with neural probe (frozen encoder + MLP) \\\\\n$K^*_{\\text{binary}}$ & $\\Kempirical$ of binary (human vs.\\ machine) detectors \\\\\n$\\theta$ & AUC decision threshold (default 0.60) \\\\\n$\\auc$ & Area Under the ROC Curve (pairwise, between adjacent depths) \\\\\nJSD & Jensen--Shannon Divergence (token-level, between adjacent depths) \\\\\nOBD & Ordinal Binary Decomposition (classifier architecture) \\\\\nLOFO & Leave-One-Family-Out cross-validation \\\\\nPELT & Pruned Exact Linear Time changepoint detection \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{Supplementary Figures}\n\n\\begin{figure}[htbp]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_filtering_strategies.pdf}\n\\caption{Downstream performance of all filtering strategies (5 seeds, $\\pm$1 std). Binary-ours (green) minimizes MMLU degradation; graduated $\\alpha$ sweep shows monotonic convergence toward binary. Dashed line: base model (no fine-tuning).}\n\\label{fig:filtering_strategies}\n\\end{figure}\n\n\\begin{figure}[htbp]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{figures/fig_s1_auc_decay_ci.pdf}\n  \\caption{Pairwise $\\auc$ decay curves for five model-mode configurations with bootstrap 95\\% confidence intervals. Error bars computed from 1{,}000 bootstrap resamples. The shaded region marks the $\\Kempirical=2$ boundary where $\\auc$ drops below $\\theta=0.60$. This figure complements Figure~\\ref{fig:kstar_theta}(a) in the main text by showing statistical uncertainty for each measurement point.}\n  \\label{fig:s1_auc_decay_ci}\n\\end{figure}\n\n\\FloatBarrier\n\\section{Supplementary Tables}\n\n%%% Feature ranking table (moved from main text)\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Top-3 features by single-feature $\\auc$ ranking. Bold: shared across all continuation-mode models. Spearman $\\rho$ (continuation pairs): Pythia--OLMo 0.95, Pythia--Qwen-cont 0.91, OLMo--Qwen-cont 0.85.}\n\\label{tab:top_features}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{cllll}\n\\toprule\nRank & Pythia & OLMo & Qwen-rw & Qwen-cont \\\\\n\\midrule\n1 & \\textbf{\\texttt{surp\\_d1\\_std}} & \\textbf{\\texttt{surp\\_std}} & \\texttt{freq\\_entropy} & \\textbf{\\texttt{surp\\_d1\\_std}} \\\\\n2 & \\textbf{\\texttt{surp\\_d2\\_std}} & \\textbf{\\texttt{surp\\_d1\\_std}} & \\textbf{\\texttt{surp\\_std}} & \\textbf{\\texttt{surp\\_std}} \\\\\n3 & \\textbf{\\texttt{surp\\_std}} & \\textbf{\\texttt{surp\\_d2\\_std}} & \\textbf{\\texttt{surp\\_d1\\_std}} & \\textbf{\\texttt{surp\\_d2\\_std}} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n%%% Table S1: Cross-Transfer Confusion Matrix (exp-013)\n\\begin{table*}[t]\n  \\centering\n  \\caption{Cross-model transfer accuracy matrix. Each cell reports the six-class depth classification accuracy of a detector trained on one model's outputs (row) and evaluated on another model's outputs (column). Diagonal entries (\\textbf{bold}) indicate within-model performance. Transfer retention is computed as the ratio of off-diagonal accuracy to the geometric mean of the two corresponding diagonal entries.}\n  \\label{tab:s1_transfer}\n  \\begin{tabular}{lcccc}\n    \\toprule\n    \\multirow{2}{*}{\\textbf{Train Model}} & \\multicolumn{4}{c}{\\textbf{Test Model}} \\\\\n    \\cmidrule(lr){2-5}\n    & Qwen-rw & Pythia & OLMo & Qwen-cont \\\\\n    \\midrule\n    Qwen-rw   & \\textbf{0.4229} & 0.2590 & 0.2653 & 0.3466 \\\\\n    Pythia    & 0.2718 & \\textbf{0.3856} & 0.3531 & 0.3287 \\\\\n    OLMo      & 0.2768 & 0.3450 & \\textbf{0.3822} & 0.3244 \\\\\n    Qwen-cont & 0.3440 & 0.3284 & 0.3112 & \\textbf{0.3875} \\\\\n    \\bottomrule\n  \\end{tabular}\n  \\vspace{4pt}\n\n  \\footnotesize\n  \\textit{Transfer retention} between models $A$ and $B$ is defined as $\\frac{1}{2}\\bigl(\\frac{\\mathrm{acc}(A \\to B)}{\\sqrt{\\mathrm{acc}(A \\to A) \\cdot \\mathrm{acc}(B \\to B)}} + \\frac{\\mathrm{acc}(B \\to A)}{\\sqrt{\\mathrm{acc}(A \\to A) \\cdot \\mathrm{acc}(B \\to B)}}\\bigr)$.\n  Notable pairs: Pythia$\\leftrightarrow$OLMo 91--92\\%, Qwen-cont$\\leftrightarrow$Pythia 83--85\\%, Qwen-cont$\\leftrightarrow$OLMo 80--85\\%, Qwen-rw$\\to$Pythia/OLMo 61--63\\%.\n\\end{table*}\n\n%%% Table S2: Decoding Ablation AUC (exp-003)\n\\begin{table*}[t]\n  \\centering\n  \\caption{Pairwise AUC with bootstrap 95\\% CIs across depth pairs for four decoding configurations (all using Qwen2.5-1.5B-Instruct in rewrite mode; 10{,}000 bootstrap resamples). The horizontal rule between depth pairs 1\\,vs.\\,2 and 2\\,vs.\\,3 marks the empirical detectability boundary $\\Kempirical=2$. Bottom rows report cross-configuration Spearman $\\rho$ on per-feature discriminative-power rankings.}\n  \\label{tab:s2_decoding}\n  \\footnotesize\n  \\begin{tabular}{lcccc}\n    \\toprule\n    \\textbf{Depth Pair} & \\textbf{Greedy} & \\textbf{Nuc $p{=}0.9$, $T{=}1.0$} & \\textbf{Nuc $p{=}0.95$, $T{=}0.7$} & \\textbf{Nuc $p{=}0.95$, $T{=}1.2$} \\\\\n    \\midrule\n    0 vs.\\ 1 & $.980\\;[.977,\\,.982]$ & $.995\\;[.993,\\,.996]$ & $.988\\;[.986,\\,.990]$ & $.998\\;[.998,\\,.999]$ \\\\\n    1 vs.\\ 2 & $.689\\;[.680,\\,.698]$ & $.687\\;[.677,\\,.695]$ & $.689\\;[.680,\\,.697]$ & $.704\\;[.695,\\,.713]$ \\\\\n    \\cmidrule(lr){1-5}\n    2 vs.\\ 3 & $.561\\;[.552,\\,.571]$ & $.592\\;[.582,\\,.601]$\\rlap{$^\\dagger$} & $.590\\;[.581,\\,.600]$ & $.582\\;[.572,\\,.592]$ \\\\\n    3 vs.\\ 4 & $.540\\;[.531,\\,.550]$ & $.547\\;[.537,\\,.557]$ & $.539\\;[.529,\\,.549]$ & $.529\\;[.519,\\,.540]$ \\\\\n    4 vs.\\ 5 & $.514\\;[.503,\\,.524]$ & $.507\\;[.496,\\,.517]^{\\ddagger}$ & $.535\\;[.524,\\,.545]$ & $.524\\;[.513,\\,.535]$ \\\\\n    \\midrule\n    \\multicolumn{5}{l}{\\textbf{Cross-config feature Spearman $\\rho$}} \\\\\n    \\midrule\n    \\multicolumn{2}{l}{Greedy vs.\\ Nuc $p{=}0.9$} & 0.600 &\n    \\multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\\ $T{=}0.7$} & 0.782 \\\\\n    \\multicolumn{2}{l}{Greedy vs.\\ $T{=}0.7$} & 0.914 &\n    \\multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\\ $T{=}1.2$} & 0.893 \\\\\n    \\multicolumn{2}{l}{Greedy vs.\\ $T{=}1.2$} & 0.532 &\n    \\multicolumn{1}{l}{$T{=}0.7$ vs.\\ $T{=}1.2$} & 0.668 \\\\\n    \\bottomrule\n    \\multicolumn{5}{l}{${}^{\\dagger}$\\,CI upper bound (0.601) marginally exceeds $\\theta{=}0.60$ by 0.001.} \\\\\n    \\multicolumn{5}{l}{${}^{\\ddagger}$\\,Permutation $p = 0.12$ (not significant). All other pairs $p < 0.01$.}\n  \\end{tabular}\n\\end{table*}\n\n%%% Table S2b: Extended K* CI (all models including new additions)\n\\begin{table*}[t]\n  \\centering\n  \\footnotesize\n  \\caption{Extended pairwise $\\auc$ with bootstrap 95\\% CIs for 9 C4 configurations (Gemma-2-2B reported in Table~\\ref{tab:domain_kstar}).\n  This table extends Table~\\ref{tab:kstar_ci} in the main text with Qwen-base, Qwen-14B, LLaMA-8B, and Mistral-7B.\n  7/9 continuation-mode configurations yield $\\Kempirical = 2$; Mistral-7B yields $\\Kempirical = 1$; Qwen-rw$^\\dagger$ is rewrite mode (ablation).}\n  \\label{tab:kstar_ci_extended}\n  \\resizebox{\\textwidth}{!}{%\n  \\begin{tabular}{lcccccccccccccccccc}\n    \\toprule\n     & \\multicolumn{2}{c}{Qwen-rw\\rlap{$^\\dagger$}} & \\multicolumn{2}{c}{Pythia} & \\multicolumn{2}{c}{OLMo} & \\multicolumn{2}{c}{Qwen-cont} & \\multicolumn{2}{c}{Qwen-7B\\rlap{$^\\ddagger$}} & \\multicolumn{2}{c}{Qwen-14B\\rlap{$^\\ddagger$}} & \\multicolumn{2}{c}{Qwen-base} & \\multicolumn{2}{c}{LLaMA-8B} & \\multicolumn{2}{c}{Mistral-7B} \\\\\n    \\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\\cmidrule(lr){6-7}\\cmidrule(lr){8-9}\\cmidrule(lr){10-11}\\cmidrule(lr){12-13}\\cmidrule(lr){14-15}\\cmidrule(lr){16-17}\\cmidrule(lr){18-19}\n     & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI \\\\\n    \\midrule\n    0v1 & .9956 & & .9932 & & .9970 & & .9971 & & .9638 & [.961,\\,.967] & .960 & [.956,\\,.963] & .987 & [.985,\\,.989] & .9225 & [.918,\\,.927] & .930 & [.925,\\,.935] \\\\\n    1v2 & .6955 & [.686,\\,.704]\\rlap{$^*$} & .6539 & [.645,\\,.663]\\rlap{$^*$} & .6145 & [.605,\\,.625]\\rlap{$^*$} & .6112 & [.602,\\,.621]\\rlap{$^*$} & .6168 & [.608,\\,.626]\\rlap{$^*$} & .621 & [.612,\\,.630]\\rlap{$^*$} & .626 & [.617,\\,.635]\\rlap{$^*$} & .6123 & [.603,\\,.622]\\rlap{$^*$} & .594 & [.584,\\,.603] \\\\\n    2v3 & .5893 & [.580,\\,.599] & .5514 & [.542,\\,.563] & .5496 & [.540,\\,.560] & .5609 & [.551,\\,.571] & .5492 & [.539,\\,.559] & .549 & [.539,\\,.559] & .550 & [.540,\\,.560] & .5518 & [.542,\\,.562] & .548 & [.538,\\,.558] \\\\\n    3v4 & .5435 & & .5152 & & .5091 & & .5409 & & .5276 & & .524 & [.514,\\,.535] & .529 & [.519,\\,.540] & .5203 & [.510,\\,.531] & .521 & \\\\\n    4v5 & .5340 & & .5136 & & .5045 & & .5141 & & .5085 & & .515 & [.505,\\,.527] & .518 & [.508,\\,.529] & .5089 & [.499,\\,.519] & .510 & \\\\\n    \\bottomrule\n    \\multicolumn{19}{l}{\\footnotesize $^*$Permutation $p < 0.001$ for all boundary comparisons. Mistral-7B 1v2: $p = 0.001$ but $\\auc < \\theta$, hence $\\Kempirical{=}1$.} \\\\\n    \\multicolumn{19}{l}{\\footnotesize $^\\dagger$Rewrite mode (ablation); excluded from continuation-mode $\\Kempirical$ claim.} \\\\\n    \\multicolumn{19}{l}{\\footnotesize $^\\ddagger$Qwen-7B: Qwen2.5-7B (fp16); Qwen-14B: Qwen2.5-14B; scorer: Qwen2.5-1.5B.}\n  \\end{tabular}}\n\n\\end{table*}\n\n%%% Table S3: LLM Zero-Shot Confusion Matrices (exp-011)\n\\begin{table*}[t]\n  \\centering\n  \\caption{LLM zero-shot depth classification: $5{\\times}5$ confusion matrices\n    (Exp-011). Both frontier LLMs achieve high binary detection accuracy\n    (GPT-5.5: 0.8780; Claude Opus~4.6: 0.8818) but near-chance 5-class\n    accuracy (${\\sim}0.33$ vs.\\ OBD-LightGBM baseline 0.386, evaluated on the full test set $N{=}5{,}000$). GPT-5.5\n    strongly identifies depth-0 text (recall${=}0.7700$) but collapses on\n    depth-4 (recall${=}0.0800$), misclassifying 50/100 depth-4 samples as\n    depth-2. Claude Opus~4.6 shows more uniform errors across depths 1--4,\n    with depth-4 recall (0.3700) substantially exceeding GPT-5.5.\n    Per-depth recall comparison with OBD-LightGBM in Table~\\ref{tab:s3c_perdepth}.}\n  \\label{tab:s3_llm_zeroshot}\n\n  \\vspace{0.5em}\n  \\begin{subtable}{0.48\\textwidth}\n    \\centering\n    \\caption{GPT-5.5 ($N{=}500$, acc${=}0.332$, MAE${=}1.102$)}\n    \\label{tab:s3a_gpt55}\n    \\small\n    \\begin{tabular}{lcccccc}\n      \\toprule\n      & \\multicolumn{5}{c}{Predicted Depth} & \\\\\n      \\cmidrule(lr){2-6}\n      True & 0 & 1 & 2 & 3 & 4 & Rec. \\\\\n      \\midrule\n      0 & \\textbf{77} & 18 &  4 &  0 &  1 & .770 \\\\\n      1 &  9 & \\textbf{19} & 36 & 24 & 12 & .190 \\\\\n      2 &  8 & 10 & \\textbf{38} & 35 &  9 & .380 \\\\\n      3 & 10 & 16 & 35 & \\textbf{24} & 15 & .240 \\\\\n      4 & 11 & 13 & 50 & 18 &  \\textbf{8} & .080 \\\\\n      \\bottomrule\n    \\end{tabular}\n  \\end{subtable}\n  \\hfill\n  \\begin{subtable}{0.48\\textwidth}\n    \\centering\n    \\caption{Claude Opus~4.6 ($N{=}499$, acc${=}0.331$, MAE${=}1.150$)}\n    \\label{tab:s3b_claude}\n    \\small\n    \\begin{tabular}{lcccccc}\n      \\toprule\n      & \\multicolumn{5}{c}{Predicted Depth} & \\\\\n      \\cmidrule(lr){2-6}\n      True & 0 & 1 & 2 & 3 & 4 & Rec. \\\\\n      \\midrule\n      0 & \\textbf{69} & 26 &  3 &  0 &  2 & .690 \\\\\n      1 &  8 & \\textbf{21} & 32 & 11 & 28 & .210 \\\\\n      2 &  6 & 36 & \\textbf{28} &  5 & 25 & .280 \\\\\n      3 &  7 & 20 & 31 & \\textbf{10} & 31 & .100 \\\\\n      4 &  7 & 28 & 22 &  6 & \\textbf{37} & .370 \\\\\n      \\bottomrule\n    \\end{tabular}\n  \\end{subtable}\n\\end{table*}\n\n\\begin{table}[htbp]\n  \\centering\n  \\small\n  \\caption{Per-depth recall (\\%) on balanced $N{=}500$ test set. OBD's nominal overall accuracy gap originates from depth-0; all methods fail at depths $\\geq 2$, consistent with $\\Kempirical = 2$.}\n  \\label{tab:s3c_perdepth}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lccccc}\n    \\toprule\n    & Depth 0 & Depth 1 & Depth 2 & Depth 3 & Depth 4 \\\\\n    \\midrule\n    OBD-LightGBM & \\textbf{96} & \\textbf{39} & 14 & 19 & 22 \\\\\n    GPT-5.5      & 77 & 19 & \\textbf{38} & \\textbf{24} &  8 \\\\\n    Claude Opus~4.6 & 69 & 21 & 28 & 10 & \\textbf{37} \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n\\paragraph{Zero-shot prompt template.}\nBoth GPT-5.5 and Claude Opus~4.6 received the following system prompt (temperature 0, single-token output constraint):\n\n\\begin{quote}\n\\small\n\\texttt{The following text passage was produced through recursive LLM generation starting from human-written text (depth~0). Each successive generation feeds the previous output back to the LLM: depth~0 = human, depth~1 = first LLM pass, depth~2 = second pass, etc.}\n\n\\texttt{Estimate the generational depth (0, 1, 2, 3, or 4) of the passage below. Respond with only the depth number.}\n\n\\texttt{Text: \\{text\\}}\n\\end{quote}\n\n%%% Table: Token Length and EOS Truncation Analysis\n\\begin{table*}[t]\n  \\centering\n  \\small\n  \\caption{Mean subword token count per depth and EOS truncation rate (\\%) for depth~1+ across all model configurations (generation limit: 256 tokens). Depth~0 (human text) is shared across configurations. Depths 1--5 show no systematic length trend within any model; the 0v1 length asymmetry (human texts shorter) makes detection \\emph{more conservative}, not inflated. See Section~\\ref{sec:length_confound} for discussion.}\n  \\label{tab:token_length}\n  \\begin{tabular}{lcccccccc}\n    \\toprule\n    & \\multicolumn{6}{c}{\\textbf{Mean Token Count}} & & \\\\\n    \\cmidrule(lr){2-7}\n    \\textbf{Model} & Depth 0 & Depth 1 & Depth 2 & Depth 3 & Depth 4 & Depth 5 & \\textbf{EOS Trunc.\\ (\\%)} & \\textbf{Severity} \\\\\n    \\midrule\n    Qwen-rw (1.5B)  & 191 & 254 & 252 & 254 & 254 & 254 & 7--11 & Mild \\\\\n    Pythia-1.4B      & 192 & 214 & 215 & 216 & 217 & 218 & 34--36 & High \\\\\n    OLMo-1B          & 192 & 256 & 256 & 256 & 256 & 256 & $<$1 & Negligible \\\\\n    Qwen-cont (1.5B) & 191 & 244 & 238 & 240 & 240 & 238 & 17--20 & Moderate \\\\\n    Qwen-7B          & 191 & 196 & 195 & 193 & 197 & 197 & 45--47 & High \\\\\n    \\midrule\n    \\multicolumn{9}{l}{\\textit{Decoding ablation (Qwen-rw 1.5B)}} \\\\\n    \\quad Greedy          & 191 & 253 & 252 & 253 & 254 & 254 & 8--12 & Mild \\\\\n    \\quad Nuc $p{=}0.9$   & 191 & 254 & 251 & 254 & 253 & 254 & 8--16 & Mild \\\\\n    \\quad $T{=}0.7$       & 191 & 253 & 251 & 253 & 253 & 254 & 8--14 & Mild \\\\\n    \\quad $T{=}1.2$       & 191 & 254 & 252 & 253 & 254 & 254 & 8--16 & Mild \\\\\n    \\bottomrule\n  \\end{tabular}\n\n  \\vspace{4pt}\n  \\footnotesize\n  EOS truncation rate: percentage of depth~1+ samples where generation terminated via EOS before reaching the 256-token limit. Ranges span depths 1--5.\n\\end{table*}\n\n%%% Table S4: Dataset Statistics\n\\begin{table}[htbp]\n  \\centering\n  \\small\n  \\caption{Dataset statistics for the generational depth corpus. Depth~0 contains human-written seed texts sampled from the C4 English validation split and truncated to 256 subword tokens. Depths~1--5 are recursively generated by Qwen2.5-1.5B-Instruct (nucleus sampling, $p{=}0.95$, $T{=}1.0$). Token counts use whitespace tokenization. Statistics shown for the primary Qwen-rewrite corpus; the other three model-mode configurations (Pythia-cont, OLMo-cont, Qwen-cont) share the same generation pipeline and corpus structure.}\n  \\label{tab:s4_dataset_stats}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{clrl}\n    \\toprule\n    \\textbf{Depth} & \\textbf{$N$ samples} & \\textbf{Mean tokens} & \\textbf{Source} \\\\\n    \\midrule\n    0 & 5{,}000 & 147.8 & C4 validation (human) \\\\\n    1 & 5{,}000 & 207.1 & Qwen2.5-1.5B rewrite \\\\\n    2 & 5{,}000 & 206.1 & Qwen2.5-1.5B rewrite \\\\\n    3 & 5{,}000 & 208.0 & Qwen2.5-1.5B rewrite \\\\\n    4 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\\\\n    5 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\\\\n    \\midrule\n    \\multicolumn{2}{l}{Total} & \\multicolumn{2}{l}{30{,}000 samples} \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n%%% Table S5: Complete 15-D Feature Descriptions\n\\begin{table*}[t]\n  \\centering\n  \\caption{Complete description of the 15-dimensional feature set used by the OBD classifier. Features are grouped into three families: surprisal statistics (9~dims) computed from Qwen2.5-1.5B token-level log-probabilities, lexical diversity (3~dims), and frequency tail shape (3~dims). All features are computed per document.}\n  \\label{tab:s5_features}\n  \\begin{tabular}{llp{0.45\\textwidth}l}\n    \\toprule\n    \\textbf{Group} & \\textbf{Feature} & \\textbf{Description} & \\textbf{Range} \\\\\n    \\midrule\n    \\multirow{9}{*}{\\rotatebox[origin=c]{90}{\\textsc{Surprisal}}}\n    & \\texttt{surp\\_mean}   & Mean token surprisal $\\frac{1}{T}\\sum_t -\\log p(x_t \\mid x_{&lt;t})$ & $\\mathbb{R}^+$ \\\\\n    & \\texttt{surp\\_std}    & Standard deviation of token surprisal & $\\mathbb{R}^+$ \\\\\n    & \\texttt{surp\\_skew}   & Skewness of the surprisal distribution & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_kurt}   & Excess kurtosis of the surprisal distribution & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d1\\_mean} & Mean of first-order surprisal differences $\\Delta s_t = s_{t+1} - s_t$ & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d1\\_std}  & Std of first-order surprisal differences & $\\mathbb{R}^+$ \\\\\n    & \\texttt{surp\\_d1\\_skew} & Skewness of first-order surprisal differences & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d2\\_mean} & Mean of second-order differences $\\Delta^2 s_t$ & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d2\\_std}  & Std of second-order surprisal differences & $\\mathbb{R}^+$ \\\\\n    \\midrule\n    \\multirow{3}{*}{\\rotatebox[origin=c]{90}{\\textsc{Lex}}}\n    & \\texttt{ttr}          & Type-token ratio: $|V| / T$ & $[0, 1]$ \\\\\n    & \\texttt{hapax\\_ratio} & Hapax legomena ratio: freq-1 types / unique types & $[0, 1]$ \\\\\n    & \\texttt{self\\_bleu}   & Mean 4-gram BLEU against 100 random same-depth samples & $[0, 1]$ \\\\\n    \\midrule\n    \\multirow{3}{*}{\\rotatebox[origin=c]{90}{\\textsc{Freq}}}\n    & \\texttt{freq\\_kurtosis}  & Excess kurtosis of word frequency distribution & $\\mathbb{R}$ \\\\\n    & \\texttt{freq\\_entropy}   & Shannon entropy of word frequencies: $-\\sum p_w \\log_2 p_w$ & $\\mathbb{R}^+$ \\\\\n    & \\texttt{low\\_freq\\_ratio} & Proportion of vocabulary with count $\\leq 2$ & $[0, 1]$ \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table*}\n\n%%% Tables S6 & S7: Side by side in a single table* to avoid table*/table overlap\n\\begin{table*}[t]\n\\begin{minipage}[t]{0.45\\textwidth}\n  \\centering\n  \\small\n  \\captionof{table}{LightGBM hyperparameters for the pairwise OBD (Ordinal Binary Decomposition) classifier used throughout the paper. One binary classifier is trained per adjacent depth pair $(k, k{+}1)$; 5-fold GroupKFold cross-validation is grouped by \\texttt{doc\\_id} to prevent data leakage from the same seed document appearing in both train and test.}\n  \\label{tab:s6_lgbm_params}\n  \\begin{tabular}{ll}\n    \\toprule\n    \\textbf{Parameter} & \\textbf{Value} \\\\\n    \\midrule\n    \\texttt{n\\_estimators}      & 200 \\\\\n    \\texttt{learning\\_rate}     & 0.05 \\\\\n    \\texttt{max\\_depth}         & 6 \\\\\n    \\texttt{num\\_leaves}        & 31 \\\\\n    \\texttt{verbose}            & $-1$ \\\\\n    \\texttt{n\\_jobs}            & $-1$ (all cores) \\\\\n    Cross-validation            & 5-fold GroupKFold \\\\\n    Grouping key                & \\texttt{doc\\_id} \\\\\n    Objective                   & Binary (per depth pair) \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{minipage}\\hfill\n\\begin{minipage}[t]{0.52\\textwidth}\n  \\centering\n  \\small\n  \\captionof{table}{Neural probe architecture and training details (Exp-015). Applied to all three model families (Qwen2.5-1.5B, Pythia-1.4B, OLMo-1B): each model's frozen hidden states are average-pooled into document embeddings and classified by a two-hidden-layer MLP.}\n  \\label{tab:s7_neural_probe}\n  \\resizebox{\\textwidth}{!}{%\n  \\begin{tabular}{ll}\n    \\toprule\n    \\textbf{Component} & \\textbf{Details} \\\\\n    \\midrule\n    \\multicolumn{2}{l}{\\textit{Embedding extraction}} \\\\\n    Base models       & Qwen2.5-1.5B / Pythia-1.4B / OLMo-1B (frozen) \\\\\n    Representation    & Last hidden state, attention-masked avg pool \\\\\n    Embedding dim     & 1536 / 2048 / 2048 \\\\\n    Max sequence len   & 512 tokens \\\\\n    \\midrule\n    \\multicolumn{2}{l}{\\textit{MLP classifier}} \\\\\n    Architecture      & $d_{\\text{emb}} \\to 512 \\to 256 \\to 6$ \\\\\n    Activations       & ReLU \\\\\n    Dropout           & 0.1 (after each hidden layer) \\\\\n    Output            & 6-class softmax \\\\\n    \\midrule\n    \\multicolumn{2}{l}{\\textit{Training}} \\\\\n    Optimizer         & Adam ($\\text{lr} = 10^{-3}$, weight decay $= 10^{-4}$) \\\\\n    Loss              & Cross-entropy \\\\\n    Batch size        & 256 \\\\\n    Max epochs        & 20 \\\\\n    Early stopping    & Patience = 5 (validation loss) \\\\\n    Cross-validation  & 5-fold GroupKFold \\\\\n    \\bottomrule\n  \\end{tabular}%\n  }\n\\end{minipage}\n\\end{table*}\n\n%%% Table S9: Binary Detector Spearman ρ (exp-012)\n\\begin{table*}[t]\n  \\centering\n  \\small\n  \\caption{Spearman rank correlation ($\\rho$) between binary detector confidence scores and true generational depth, and 6-class depth classification accuracy (Exp-012). Three metrics: log-PPL from the reference model (DivEye), log-PPL from the observer model, and PPL ratio (Binoculars; observer: Pythia-1.4B, performer: OLMo-1B). Random baseline for 6-class accuracy: 0.167. While statistically significant, correlations are driven by the 0v1 boundary; confidence scores do not monotonically track depth beyond generation~1. Qwen-rewrite exhibits reversed sign ($\\rho > 0$), indicating that generation mode alters the direction of binary confidence's relationship with depth.}\n  \\label{tab:s9_binary_spearman}\n  \\begin{tabular}{lcccc}\n    \\toprule\n    & \\textbf{Qwen-rw} & \\textbf{Pythia} & \\textbf{OLMo} & \\textbf{Qwen-cont} \\\\\n    \\midrule\n    \\multicolumn{5}{l}{\\textit{Spearman $\\rho$ with true depth}} \\\\\n    \\quad log-PPL (ref)      & $-0.123$ & $-0.297$ & $-0.378$ & $-0.389$ \\\\\n    \\quad log-PPL (observer) & $+0.082$ & $-0.453$ & $-0.461$ & $-0.162$ \\\\\n    \\quad PPL ratio           & $+0.119$ & $-0.392$ & $-0.407$ & $-0.058$ \\\\\n    \\midrule\n    \\multicolumn{5}{l}{\\textit{Classification}} \\\\\n    \\quad 6-class accuracy    & 0.199    & 0.130    & 0.127    & 0.183 \\\\\n    \\midrule\n    \\multicolumn{5}{l}{Random baseline: 0.167 \\quad $K^*_{\\text{binary}} = 1$ \\quad $K^*_{\\text{OBD}} = 2$} \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table*}\n\n%%% Table S10: Pythia Decoding Ablation (exp-020)\n\\begin{table*}[t]\n  \\centering\n  \\small\n  \\caption{Pairwise $\\auc$ with bootstrap 95\\% CIs across depth pairs for Pythia-1.4B under four decoding configurations (Exp-020; 10{,}000 bootstrap resamples). Complements Table~\\ref{tab:s2_decoding} (Qwen-rewrite) with a second model family. $^\\dagger$Greedy decoding triggers repetition collapse in Pythia-1.4B (4-gram repeat rate: $d_0{=}0.01 \\to d_1{=}0.72$), inflating 0v1 and 1v2 AUC via lexical degeneracy rather than depth-discriminative features.}\n  \\label{tab:s10_pythia_decoding}\n  \\begin{tabular}{lcccc}\n    \\toprule\n    \\textbf{Depth Pair} & \\textbf{Greedy}$^\\dagger$ & \\textbf{Nuc $p{=}0.9$, $T{=}1.0$} & \\textbf{Nuc $p{=}0.95$, $T{=}0.7$} & \\textbf{Nuc $p{=}0.95$, $T{=}1.2$} \\\\\n    \\midrule\n    0 vs.\\ 1 & .9992 & .9948 & .9965 & .9933 \\\\\n    1 vs.\\ 2 & .8838 & .6770 & .7265 & .6172 \\\\\n    \\cmidrule(lr){1-5}\n    2 vs.\\ 3 & .5342 & .5549 & .5941 & .5226 \\\\\n    3 vs.\\ 4 & .5228 & .5299 & .5698 & .5170 \\\\\n    4 vs.\\ 5 & .5162 & .5013 & .5284 & .5051 \\\\\n    \\midrule\n    $\\Kempirical$ & 2 & 2 & 2 & 2 \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table*}\n\n%%% Table S11: Length Ablation (exp-021)\n\\begin{table*}[t]\n  \\centering\n  \\small\n  \\caption{Pairwise $\\auc$ across depth pairs for three segment lengths (Exp-021; Qwen2.5-1.5B base, continuation mode). $\\Kempirical{=}2$ is confirmed for 128 and 256 tokens; 512 tokens yields point estimate $\\Kempirical{=}2$ but the 1v2 bootstrap CI lower bound falls marginally below $\\theta$.}\n  \\label{tab:s11_length_ablation}\n  \\begin{tabular}{lccc}\n    \\toprule\n    \\textbf{Depth Pair} & \\textbf{128 tokens} & \\textbf{256 tokens} & \\textbf{512 tokens} \\\\\n    \\midrule\n    0 vs.\\ 1 & .9948 & .9956 & .9961 \\\\\n    1 vs.\\ 2 & .6219 & .6282 & .6073$^\\dagger$ \\\\\n    \\cmidrule(lr){1-4}\n    2 vs.\\ 3 & .5531 & .5609 & .5482 \\\\\n    3 vs.\\ 4 & .5218 & .5305 & .5196 \\\\\n    4 vs.\\ 5 & .5104 & .5142 & .5078 \\\\\n    \\midrule\n    $\\Kempirical$ & 2 & 2 & 2$^\\dagger$ \\\\\n    \\bottomrule\n    \\multicolumn{4}{l}{\\footnotesize $^\\dagger$CI $[0.5979,\\,0.6166]$; lower bound ${<}\\theta{=}0.60$.}\n  \\end{tabular}\n\\end{table*}\n\n%%% Table S12: Domain Ablation\n\\begin{table*}[t]\n  \\centering\n  \\small\n  \\caption{Pairwise $\\auc$ across depth pairs for three text domains (Qwen2.5-1.5B base, continuation mode). Tests generalization of $\\Kempirical{=}2$ beyond C4 web text to structured and technical domains. Same-family scoring (Qwen-1.5B); cross-family controlled values in Table~\\ref{tab:wiki_domain}.}\n  \\label{tab:s12_domain_ablation}\n  \\begin{tabular}{lccc}\n    \\toprule\n    \\textbf{Depth Pair} & \\textbf{C4 (web)} & \\textbf{Wikipedia} & \\textbf{arXiv} \\\\\n    \\midrule\n    0 vs.\\ 1 & .9971 & .996 & .9984 \\\\\n    1 vs.\\ 2 & .6112 & .6193 & .8580 \\\\\n    \\cmidrule(lr){1-4}\n    2 vs.\\ 3 & .5609 & .556 & .6427 \\\\\n    3 vs.\\ 4 & .5409 & .528 & .5813 \\\\\n    4 vs.\\ 5 & .5141 & .509 & .5346 \\\\\n    \\midrule\n    $\\Kempirical$ & 2 & 2 & 3 \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table*}\n\n%%% Table S13: Scorer Sensitivity Analysis\n\\begin{table*}[t]\n  \\centering\n  \\small\n  \\caption{Scorer sensitivity: $\\Kempirical$ under self-scoring vs.\\ cross-scoring. Self-scorer uses the generator's own model family for feature extraction; cross-scorer uses alternative models (Pythia-1.4B, OLMo-1B). $\\Kempirical$ agreement across scorer conditions indicates the boundary is governed by the generation process. Cross-scoring reduces $\\Kempirical$ only for the most marginal self-scorer condition (Qwen-continuation).}\n  \\label{tab:s13_scorer_sensitivity}\n  \\begin{tabular}{lccccc}\n    \\toprule\n    & & \\multicolumn{3}{c}{\\textbf{Scorer}} & \\\\\n    \\cmidrule(lr){3-5}\n    \\textbf{Generator} & \\textbf{Mode} & \\textbf{Self} & \\textbf{Pythia} & \\textbf{OLMo} & \\textbf{Agreement} \\\\\n    \\midrule\n    Qwen-1.5B-Instruct & Rewrite      & 2 (.696) & 2 & 2 & \\checkmark \\\\\n    Qwen-1.5B-Instruct & Continuation & 2 (.611) & 1 & 1 & $\\times$ \\\\\n    Qwen-1.5B (base)   & Continuation & 2 (.626) & 2 & 2 & \\checkmark \\\\\n    Pythia-1.4B         & Continuation & 2 (.654) & 2 & 2 & \\checkmark \\\\\n    OLMo-1B             & Continuation & 2 (.615) & 2 & 2 & \\checkmark \\\\\n    Qwen-7B             & Continuation & 2 (.618) & 2 & 2 & \\checkmark \\\\\n    Mistral-7B          & Continuation & 1 (.594) & 1 & 1 & \\checkmark \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table*}\n\n",
      "numLines": 492,
      "startLine": 1,
      "totalLines": 492
    }
  },
  "sourceToolAssistantUUID": "339f316b-5f29-49a4-a246-50958af13b33",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 39_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "7226b6af-0ed4-40b9-8ac1-d70c399176c1",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 40_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Tool result

_source line 41 · 2026-05-21T06:34:52.585Z_

<details><summary>↩ Tool result · reported error · `toolu_01K88WtKU97xUVTNqSgCZRkW`</summary>

```text
File content (30357 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "76357251-4f7d-4853-9c72-c5ad173193d4",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "5f53659e-1f45-4d26-9fd1-73f52aebdcc1",
  "toolUseResult": "Error: File content (30357 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "76357251-4f7d-4853-9c72-c5ad173193d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 42 · 2026-05-21T06:34:52.591Z_

```json
{
  "parentUuid": "5f53659e-1f45-4d26-9fd1-73f52aebdcc1",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "5ea0b772-7f05-4c17-bb3d-e093ab7d056b",
  "timestamp": "2026-05-21T06:34:52.591Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 43 · 2026-05-21T06:34:58.694Z_

<details><summary>Logged reasoning block</summary>

```text
The appendix_extended.tex is too large. Let me read it in chunks. But first, let me also read the table files to be thorough.

Actually, let me focus on what I need for the content audit. I've read the main content files. The appendix_extended is supplementary material. Let me read the first portion to understand its structure, and then specific portions if needed.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5ea0b772-7f05-4c17-bb3d-e093ab7d056b",
  "isSidechain": false,
  "requestId": "req_011CbFFQqgWTg5GJGrJkH8kC",
  "type": "assistant",
  "uuid": "a055e790-5a30-4cd2-97e2-5675fe9dd408",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvLQxtAWK5eoqbQjfJjWm6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 30058,
      "cache_read_input_tokens": 50064,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 30058,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 458,
          "cache_read_input_tokens": 50064,
          "cache_creation_input_tokens": 30058,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 30058
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-21T06:34:59.023Z_

读取 appendix_extended 分段和表格文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a055e790-5a30-4cd2-97e2-5675fe9dd408",
  "isSidechain": false,
  "requestId": "req_011CbFFQqgWTg5GJGrJkH8kC",
  "type": "assistant",
  "uuid": "05c1b4de-ef65-4a6a-9d4f-09acd023c543",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvLQxtAWK5eoqbQjfJjWm6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 30058,
      "cache_read_input_tokens": 50064,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 30058,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 458,
          "cache_read_input_tokens": 50064,
          "cache_creation_input_tokens": 30058,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 30058
          },
          "type": "message"
        }
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

_source line 45 · 2026-05-21T06:35:00.909Z_

<details open><summary>🔧 Tool call — Read · `toolu_01U1WnyTXHRpvjH9Y3XTeLNv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "05c1b4de-ef65-4a6a-9d4f-09acd023c543",
  "isSidechain": false,
  "requestId": "req_011CbFFQqgWTg5GJGrJkH8kC",
  "type": "assistant",
  "uuid": "a09dfb67-fd0c-4bce-bbb5-8fac95aa0d06",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvLQxtAWK5eoqbQjfJjWm6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 30058,
      "cache_read_input_tokens": 50064,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 30058,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 458,
          "cache_read_input_tokens": 50064,
          "cache_creation_input_tokens": 30058,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 30058
          },
          "type": "message"
        }
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

_source line 46 · 2026-05-21T06:35:02.964Z_

<details><summary>↩ Tool result · `toolu_019yKUChbHgowryD2d9WBY16`</summary>

```text
1	{\small
2	\begin{tabular}{llcccc}
3	\toprule
4	\textbf{Scorer} & \textbf{Gen.\ Data} & $\boldsymbol{K^*}$ & \textbf{AUC(0v1)} & \textbf{AUC(1v2)} & \textbf{Spearman}~$\boldsymbol{\rho}$ \\
5	\midrule
6	% --- Qwen-RW block ---
7	Qwen-1.5B (self) & Qwen-RW & 2 & --- & 0.6955 & --- \\
8	Pythia-1.4B       & Qwen-RW & 2 & 0.9923 & 0.7012 & 0.906 \\
9	OLMo-1B           & Qwen-RW & 2 & 0.9918 & 0.6947 & 0.920 \\
10	\midrule
11	% --- Qwen-cont block ---
12	Qwen-1.5B (self) & Qwen-cont & 2 & --- & 0.6112 & --- \\
13	Pythia-1.4B       & Qwen-cont & \textcolor{red}{1\textsuperscript{$\dagger$}} & 0.9900 & \underline{0.5923} & 0.942 \\
14	OLMo-1B           & Qwen-cont & \textcolor{red}{1\textsuperscript{$\dagger$}} & 0.9890 & \underline{0.5858} & 0.902 \\
15	\midrule
16	% --- Qwen-7B cross-scale block ---
17	Qwen-1.5B        & Qwen-7B-cont & 2 & 0.9644 & 0.6178 & --- \\
18	\bottomrule
19	\end{tabular}
20	}
21	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3db4e1a0-8f41-4c69-85dd-98a40426cfb3",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "b4ecc4e0-ffe7-4cf7-8f93-34b0f14be6d7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_crossscorer.tex",
      "content": "{\\small\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Scorer} & \\textbf{Gen.\\ Data} & $\\boldsymbol{K^*}$ & \\textbf{AUC(0v1)} & \\textbf{AUC(1v2)} & \\textbf{Spearman}~$\\boldsymbol{\\rho}$ \\\\\n\\midrule\n% --- Qwen-RW block ---\nQwen-1.5B (self) & Qwen-RW & 2 & --- & 0.6955 & --- \\\\\nPythia-1.4B       & Qwen-RW & 2 & 0.9923 & 0.7012 & 0.906 \\\\\nOLMo-1B           & Qwen-RW & 2 & 0.9918 & 0.6947 & 0.920 \\\\\n\\midrule\n% --- Qwen-cont block ---\nQwen-1.5B (self) & Qwen-cont & 2 & --- & 0.6112 & --- \\\\\nPythia-1.4B       & Qwen-cont & \\textcolor{red}{1\\textsuperscript{$\\dagger$}} & 0.9900 & \\underline{0.5923} & 0.942 \\\\\nOLMo-1B           & Qwen-cont & \\textcolor{red}{1\\textsuperscript{$\\dagger$}} & 0.9890 & \\underline{0.5858} & 0.902 \\\\\n\\midrule\n% --- Qwen-7B cross-scale block ---\nQwen-1.5B        & Qwen-7B-cont & 2 & 0.9644 & 0.6178 & --- \\\\\n\\bottomrule\n\\end{tabular}\n}\n",
      "numLines": 21,
      "startLine": 1,
      "totalLines": 21
    }
  },
  "sourceToolAssistantUUID": "3db4e1a0-8f41-4c69-85dd-98a40426cfb3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 47 · 2026-05-21T06:35:00.933Z_

<details><summary>↩ Tool result · `toolu_01U1WnyTXHRpvjH9Y3XTeLNv`</summary>

```text
1	\section{Extended Analysis and Limitations}
2	\label{sec:extended_discussion}
3	
4	This section provides supporting tables for cross-scorer validation (Tables~\ref{tab:crossscorer}--\ref{tab:anova_crossscorer}), followed by extended limitations, ablation studies, and domain-specific analyses.
5	
6	\begin{table}[htbp]
7	\centering
8	\small
9	\caption{Cross-scorer validation on Qwen-generated text. Alternative scorers (Pythia-1.4B, OLMo-1B) preserve feature ranking ($\rho > 0.90$) and rewrite-mode $\Kempirical = 2$, but reduce continuation-mode $\Kempirical$ from 2 to 1.}
10	\label{tab:crossscorer}
11	\resizebox{\columnwidth}{!}{\input{tables/tab_crossscorer}}
12	\end{table}
13	
14	\begin{table}[htbp]
15	\centering
16	\small
17	\caption{Three-way ANOVA (Generator $\times$ Scorer $\times$ Depth-Pair) on per-fold pairwise $\auc$ values (Type~II SS). DV = per-fold AUC; $N{=}300$ (12 cells $\times$ 5 folds $\times$ 5 depth-pairs; 3 generators $\times$ 4 scorers). Scorer is statistically significant ($p < .001$) but has a small effect size ($\eta^2_p = 0.19$) relative to Depth-Pair ($\eta^2_p = 1.00$) and Generator ($\eta^2_p = 0.89$), indicating that scorer choice has a detectable but practically minor influence on depth discrimination (Scorer $\eta^2_p$ is approximately 5$\times$ smaller than Generator and dwarfed by Depth-Pair). Per-fold AUC values within the same generator share seed documents across folds and are not fully independent; we therefore rely on effect-size ratios rather than $p$-values for interpretation.}
18	\label{tab:anova_crossscorer}
19	\begin{tabular}{lrrrr}
20	\toprule
21	\textbf{Source} & \textbf{df} & $F$ & $p$ & $\eta^2_p$ \\
22	\midrule
23	Generator     & 2  & 926.8  & ${<}.001$  & .885 \\
24	Scorer        & 3  & 19.02  & ${<}.001$  & .192 \\
25	Depth-Pair    & 4  & 24736  & ${<}.001$  & .998 \\
26	Gen$\times$Scorer & 6 & 8.16 & ${<}.001$ & .170 \\
27	Gen$\times$Depth  & 8 & 993.7 & ${<}.001$ & .971 \\
28	Scorer$\times$Depth & 12 & 2.45 & .005 & .109 \\
29	Residual      & 240 & & & \\
30	\bottomrule
31	\end{tabular}
32	\end{table}
33	
34	\subsection{Extended Limitations}
35	\label{sec:extended_limitations}
36	
37	\emph{Prompt-chain versus retrain-chain.}
38	Qwen2.5-1.5B and Pythia-1.4B yield $\Kempirical{=}7$ under retrain-chain LoRA fine-tuning (Table~\ref{tab:retrain_ci}), extending detectable depth by 5 additional generations beyond prompt-chain $\Kempirical{=}2$.
39	OLMo-1B reaches $\Kempirical{\geq}4$ (3v4 $\auc = 0.682$, margin 8\,pp above $\theta$; deeper pairs pending), confirming across three architecture families that retrain-chain $\Kempirical$ is protocol-determined.
40	Cumulative model-adaptation artifacts (vocabulary narrowing, repetition bias) make each retrained generation highly distinguishable.
41	The two models exhibit different decay profiles: Pythia achieves higher early-pair AUC (1v2: 0.947 vs.\ 0.897) but drops more steeply at deeper pairs (4v5: 0.691 vs.\ 0.746), yet both converge to $\Kempirical{=}7$ (6v7: Qwen 0.641, Pythia 0.634; both CI lower bounds $> \theta$).
42	This convergence despite differences in effective LoRA adaptation capacity (Pythia uses fused QKV attention with rank-16 vs.\ Qwen's separate Q/K/V projections) indicates robustness to LoRA parameterization.
43	The extended discriminability under retraining aligns with theoretical analyses of iterative retraining instability on synthetic data~\cite{bertrand2024stability, gerstgrasser2024model}, where each retraining cycle amplifies distributional artifacts beyond the text-intrinsic degradation observed in prompt-chains.
44	Extrapolating yields 7v8 $\approx 0.57 < \theta$ for both models. This places $\Kempirical{=}7$ near the ceiling for retrain-chains.
45	Prompt-chain $\Kempirical$ represents the operationally relevant boundary for data curation (text-intrinsic information loss); retrain-chain $\Kempirical$ represents the upper bound achievable via model archaeology (known training pipeline).
46	
47	\begin{table}[htbp]
48	\centering
49	\small
50	\caption{Retrain-chain pairwise $\auc$ with 5-fold CV 95\% CIs. Both models yield $\Kempirical{=}7$; all CI lower bounds $> \theta{=}0.60$. Retrain-chain CIs use fold-level estimates (Section~\ref{sec:retrain_ci_note}).}
51	\label{tab:retrain_ci}
52	\begin{tabular}{lcccc}
53	\toprule
54	 & \multicolumn{2}{c}{\textbf{Qwen-1.5B}} & \multicolumn{2}{c}{\textbf{Pythia-1.4B}} \\
55	\cmidrule(lr){2-3}\cmidrule(lr){4-5}
56	\textbf{Pair} & $\auc$ & 95\% CI & $\auc$ & 95\% CI \\
57	\midrule
58	0v1 & 0.9837 & $[.982,\,.985]$ & 0.9844 & $[.983,\,.986]$ \\
59	1v2 & 0.8971 & $[.895,\,.899]$ & 0.9470 & $[.942,\,.952]$ \\
60	2v3 & 0.8098 & $[.805,\,.814]$ & 0.8891 & $[.882,\,.896]$ \\
61	3v4 & 0.7600 & $[.753,\,.767]$ & 0.7999 & $[.795,\,.805]$ \\
62	4v5 & 0.7459 & $[.738,\,.754]$ & 0.6907 & $[.688,\,.693]$ \\
63	5v6 & 0.7017 & $[.696,\,.708]$ & 0.6497 & $[.643,\,.657]$ \\
64	6v7 & 0.6410 & $[.638,\,.645]$ & 0.6340 & $[.628,\,.641]$ \\
65	\bottomrule
66	\end{tabular}
67	\end{table}
68	
69	\paragraph{CI methodology note.}
70	\label{sec:retrain_ci_note}
71	The main pipeline reports bootstrap 95\% CIs (1{,}000 or 10{,}000 resamples), which are valid because each bootstrap sample preserves the GroupKFold document structure: resampling operates on documents, and all depths of a given document remain together.
72	In the retrain-chain setting, each generation's training corpus is the \emph{output} of the previous generation's fine-tuned model. This creates inter-generation dependencies that standard bootstrap resampling cannot preserve, and naive resampling would inflate AUC estimates.
73	Retrain-chain produces only $K{=}5$ independent training runs (one per fold), precluding meaningful document-level bootstrap resampling.
74	We therefore report fold-based 95\% CIs, computed as $\bar{x} \pm t_{0.025,\,K{-}1} \cdot s / \sqrt{K}$ from the $K{=}5$ GroupKFold AUC values ($t_{0.025,4} = 2.776$); the $t$-distribution provides conservative estimation appropriate for this small-sample regime.
75	
76	\emph{Threshold sensitivity.}
77	Table~\ref{tab:theta_sensitivity} reports $\Kempirical$ across $\theta \in [0.55, 0.70]$ for representative configurations including arXiv and cross-scorer conditions.
78	Qwen-continuation's 1v2 CI lower bound exceeds $\theta$ by only 0.2\,pp; all ten boundary comparisons yield permutation $p < 0.001$.
79	
80	\begin{table}[htbp]
81	\centering
82	\small
83	\caption{$\Kempirical$ as a function of $\theta$ across conditions. The \textbf{domain ordering} (arXiv $>$ C4 $\geq$ cross-scorer) is preserved across all $\theta$ values; absolute $\Kempirical$ shifts with $\theta$ but the hierarchy is invariant. The headline result (C4 $\Kempirical{=}2$, arXiv $\Kempirical{=}3$) holds for $\theta \in [0.575, 0.625]$.}
84	\label{tab:theta_sensitivity}
85	\resizebox{\columnwidth}{!}{%
86	\begin{tabular}{llcccccc}
87	\toprule
88	\textbf{Condition} & \textbf{Config} & $\theta{=}0.55$ & $\theta{=}0.575$ & $\theta{=}0.60$ & $\theta{=}0.625$ & $\theta{=}0.65$ & $\theta{=}0.70$ \\
89	\midrule
90	C4 (web) & Qwen-rw      & 3 & 3 & 2 & 2 & 2 & 1 \\
91	C4 (web) & Pythia       & 2 & 2 & 2 & 2 & 1 & 1 \\
92	C4 (web) & OLMo         & 2 & 2 & 2 & 1 & 1 & 1 \\
93	C4 (web) & Qwen-cont    & 2 & 2 & 2 & 2 & 1 & 1 \\
94	C4 (web) & Qwen-7B      & 2 & 2 & 2 & 2 & 1 & 1 \\
95	C4 (web) & Mistral-7B   & 2 & 2 & 1 & 1 & 1 & 1 \\
96	\midrule
97	arXiv    & Qwen-1.5B-base (cont.) & 3 & 3 & 3 & 3 & 2 & 2 \\
98	arXiv    & Pythia-1.4B (cont.)    & 3 & 3 & 3 & 3 & 2 & 2 \\
99	\midrule
100	Cross-scorer & Qwen-cont/Pythia-scored & 2 & $\approx$2 & 1 & 1 & 1 & 1 \\
101	Cross-scorer & Qwen-cont/OLMo-scored   & 2 & $\approx$1 & 1 & 1 & 1 & 1 \\
102	\bottomrule
103	\end{tabular}}
104	\end{table}
105	
106	\begin{figure}[htbp]
107	\centering
108	\includegraphics[width=\columnwidth]{figures/fig_theta_sensitivity.pdf}
109	\caption{$\Kempirical$ as a function of $\theta$ across all model $\times$ domain configurations (three panels: C4, arXiv, Wikipedia). The domain ordering (Wikipedia $\Kempirical{\leq}1$ $<$ C4 $\Kempirical{\leq}2$ $<$ arXiv $\Kempirical{\leq}3$) is preserved across the full $\theta \in [0.55, 0.70]$ range. Within each domain, inter-model variation is small relative to inter-domain differences. Source domain rather than model identity governs $\Kempirical$.}
110	\label{fig:theta_sensitivity}
111	\end{figure}
112	
113	\emph{Structural confound: token length.}
114	In continuation mode the generation prompt is discarded, so all depths $\geq 1$ consist entirely of machine-generated tokens and the 1v2 boundary compares texts differing only in conditioning context (human-authored vs.\ machine-generated prompt), not structural composition.
115	Depth~0 texts average ${\sim}$191 subword tokens (C4 truncation), while depth~1+ texts average 193--256 tokens depending on model (Table~\ref{tab:token_length}).
116	This asymmetry is directionally opposite to a length-inflation confound: shorter depth-0 texts provide less feature-extraction context, making 0v1 discrimination harder, not easier.
117	Within depths 1--5, mean token counts are stable (within-model range $\leq$ 4 tokens for all configurations except Qwen-continuation at 6 tokens), so the pairwise comparisons underlying $\Kempirical{=}2$ are unaffected by length.
118	EOS truncation rates are similarly depth-stable within each model: Qwen-rewrite 7--11\%, Pythia 34--36\%, OLMo $<$1\%, Qwen-continuation 17--20\%, Qwen-7B 45--47\%.
119	Models with the highest truncation (Pythia, Qwen-7B) still yield $\Kempirical{=}2$ with the same step-function AUC decay pattern as low-truncation models (Table~\ref{tab:kstar_ci}), EOS truncation therefore does not drive the boundary.
120	
121	\emph{Graduated filtering.}
122	All $\alpha$ values (0.1--0.9) underperform binary-ours on MMLU ($\alpha{=}0.1$: 0.5873; $\alpha{=}0.9$: 0.5892 vs.\ 0.5941); at $\alpha{=}0.9$, HellaSwag matches exactly (0.6701).
123	Binary-ours significantly outperforms all alternatives on MMLU ($p_{\text{corr}} \leq 0.021$); Graduated$_{0.9}$ is indistinguishable on HellaSwag ($p = 1.00$) but worse on MMLU ($p_{\text{corr}} = 0.011$).
124	\label{tab:pairwise_significance}
125	
126	\subsection{Dose-Response: Contamination Ratio Effect}
127	\label{sec:dose_response}
128	
129	The main filtering experiments (Section~\ref{sec:filtering}) use 100\% synthetic data to maximize effect size.
130	To characterize behavior at lower contamination ratios, we mix synthetic depths 1--5 with clean C4 at 10\%, 30\%, and 50\% contamination (Qwen-1.5B continuation, 5 seeds each; Table~\ref{tab:dose_response}).
131	
132	\begin{table}[htbp]
133	\centering
134	\small
135	\caption{MMLU and HellaSwag by contamination ratio and filtering strategy (5 seeds, mean $\pm$ std). Base model MMLU: 0.6018. Binary filtering retains a significant advantage on HellaSwag across all ratios ($p \leq 0.004$, Holm-Bonferroni corrected).}
136	\label{tab:dose_response}
137	\resizebox{\columnwidth}{!}{%
138	\begin{tabular}{lcccccc}
139	\toprule
140	& \multicolumn{2}{c}{\textbf{10\%}} & \multicolumn{2}{c}{\textbf{30\%}} & \multicolumn{2}{c}{\textbf{50\%}} \\
141	\cmidrule(lr){2-3}\cmidrule(lr){4-5}\cmidrule(lr){6-7}
142	\textbf{Strategy} & MMLU & HellaSwag & MMLU & HellaSwag & MMLU & HellaSwag \\
143	\midrule
144	No-filter   & $.6058{\pm}.0002$ & $.6689{\pm}.0006$ & $.6069{\pm}.0007$ & $.6664{\pm}.0018$ & $.6063{\pm}.0012$ & $.6680{\pm}.0005$ \\
145	Binary-ours & $\mathbf{.6079{\pm}.0004}$ & $\mathbf{.6727{\pm}.0007}$ & $\mathbf{.6082{\pm}.0011}$ & $\mathbf{.6725{\pm}.0006}$ & $\mathbf{.6088{\pm}.0009}$ & $\mathbf{.6731{\pm}.0004}$ \\
146	Graduated   & $.6066{\pm}.0010$ & $.6700{\pm}.0014$ & $.6072{\pm}.0008$ & $.6665{\pm}.0012$ & $.6062{\pm}.0008$ & $.6679{\pm}.0001$ \\
147	\bottomrule
148	\end{tabular}}
149	\end{table}
150	
151	At all tested ratios (10--50\%), no-filter MMLU remains above the base model (0.6018), synthetic data at these proportions is therefore net-beneficial rather than harmful.
152	Binary filtering consistently improves over no-filter, with HellaSwag differences significant across all ratios ($p \leq 0.004$, Holm-Bonferroni corrected).
153	MMLU differences are smaller and significant only at 10\% after correction ($p = 0.001$).
154	Graduated weighting is indistinguishable from no-filter at all ratios (MMLU $p \geq 0.27$; HellaSwag $p \geq 0.06$), depth assignments beyond $\Kempirical$ therefore inject noise regardless of contamination severity.
155	Effect sizes diminish 3--6$\times$ relative to the 100\% setting (Section~\ref{sec:filtering}), but the strategy ordering (binary $>$ graduated $\approx$ no-filter) is preserved.
156	
157	\subsection{Cross-Model Filtering Replication}
158	\label{sec:pythia_filtering}
159	
160	To test whether $\Kempirical{=}2$ correctly predicts optimal curation granularity across architectures, we replicate the filtering experiment on Pythia-1.4B (LoRA rank 8, nucleus $p{=}0.9$, $T{=}1.0$, 3 seeds; Table~\ref{tab:pythia_filtering}).
161	
162	\begin{table}[htbp]
163	\centering
164	\small
165	\caption{Pythia-1.4B filtering replication (3 seeds, mean $\pm$ std). Pythia-1.4B MMLU $\approx$ random chance (25\%), yielding low signal-to-noise; benchmark coverage is limited to 2 benchmarks (vs.\ 5 for Qwen) due to model capacity. Filtering preserves harmlessness and the graduated $\approx$ no-filter pattern holds across model families.}
166	\label{tab:pythia_filtering}
167	\begin{tabular}{lcc}
168	\toprule
169	\textbf{Strategy} & \textbf{MMLU} & \textbf{HellaSwag} \\
170	\midrule
171	No-filter & $.2568{\pm}.0012$ & $.5250{\pm}.0008$ \\
172	Binary-ours & $\mathbf{.2585{\pm}.0004}$ & $.5251{\pm}.0001$ \\
173	Graduated$_{0.9}$ & $.2561{\pm}.0009$ & $\mathbf{.5253{\pm}.0007}$ \\
174	\bottomrule
175	\end{tabular}
176	\end{table}
177	
178	Graduated filtering performs comparably to no filtering across both benchmarks, consistent with the $\Kempirical{=}2$ pattern observed on Qwen (Section~\ref{sec:filtering}).
179	The near-chance MMLU baseline (25\%) limits signal-to-noise; the key finding is that filtering remains harmless (no degradation) and the graduated $\approx$ no-filter pattern generalizes across model families, validating $\Kempirical{=}2$ as cross-architecture guidance.
180	
181	\subsection{DeBERTa vs.\ OBD Filtering Comparison}
182	\label{sec:deberta_filtering}
183	
184	To test whether DeBERTa's higher $\Kempirical$ translates into better downstream curation, we compare filtering strategies using DeBERTa-based ($\Kempirical{=}4$) and OBD-based ($\Kempirical{=}2$) depth classifiers on Qwen-1.5B C4 generations (Table~\ref{tab:deberta_filtering}).
185	
186	\begin{table}[htbp]
187	\centering
188	\small
189	\caption{DeBERTa vs.\ OBD filtering on C4 (Qwen-1.5B, single seed). OBD binary ($\Kempirical{=}2$) matches or exceeds DeBERTa binary ($\Kempirical{=}4$) on all three benchmarks; DeBERTa's higher $\Kempirical$ does not yield better filtering.}
190	\label{tab:deberta_filtering}
191	\begin{tabular}{lccc}
192	\toprule
193	\textbf{Strategy} & \textbf{MMLU} & \textbf{HellaSwag} & \textbf{ARC-C} \\
194	\midrule
195	No-filter           & .5895 & .6591 & .4352 \\
196	OBD binary (15D)    & $\mathbf{.5880}$ & $\mathbf{.6599}$ & $\mathbf{.4522}$ \\
197	DeBERTa binary      & .5870 & .6593 & .4471 \\
198	DeBERTa graduated   & .5884 & .6586 & .4420 \\
199	\bottomrule
200	\end{tabular}
201	\end{table}
202	
203	OBD binary achieves the highest HellaSwag and ARC-C scores despite using only 15 statistical features and a lower $\Kempirical$ threshold.
204	DeBERTa's richer representations and higher $\Kempirical{=}4$ do not translate into better filtering performance on web text, consistent with the representation-independent boundary at $\Kempirical{=}2$ (Section~\ref{sec:neural_probe}): the additional depth signal recovered by DeBERTa (depths 3--4) carries insufficient distributional information to improve curation.
205	The 15D OBD lower bound is practically sufficient for web text corpus filtering.
206	
207	\subsection{Contamination Rate Sensitivity}
208	\label{sec:rate_sweep}
209	
210	To characterize filtering performance across contamination severities, we vary the synthetic proportion from 10\% to 100\% (single seed, Qwen-1.5B LoRA; Table~\ref{tab:rate_sweep}).
211	Binary filtering advantage on HellaSwag increases monotonically with contamination rate ($\Delta = +0.57$\,pp at 10\%, $+0.77$\,pp at 30\%, $+1.18$\,pp at 50\%), while graduated filtering remains comparable to no filtering across all rates (max $|\Delta| \leq 0.20$\,pp on HellaSwag, $\leq 0.42$\,pp on ARC-C), consistent with $\Kempirical{=}2$: depth-weighted strategies lack discriminative signal beyond the boundary.
212	At 100\% synthetic contamination, binary filtering removes the entire corpus; real-world corpora contain a non-trivial human-authored fraction, making this boundary case practically irrelevant.
213	
214	\begin{table}[htbp]
215	\centering
216	\small
217	\caption{Contamination rate sensitivity analysis (single seed, Qwen-1.5B LoRA). Binary filtering advantage scales with contamination rate on HellaSwag and ARC-Challenge. Graduated filtering performs comparably to no filtering across all rates. MMLU differences ${<}\,0.5$\,pp across all conditions (omitted). At 100\%, binary filtering removes the entire corpus (N/A).}
218	\label{tab:rate_sweep}
219	\begin{tabular}{llcc}
220	\toprule
221	\textbf{Rate} & \textbf{Strategy} & \textbf{HellaSwag} & \textbf{ARC-C} \\
222	\midrule
223	10\% & No-filter  & .6652 & .4471 \\
224	     & Binary     & $\mathbf{.6709}$ & $\mathbf{.4462}$ \\
225	     & Graduated  & .6672 & .4428 \\
226	\midrule
227	30\% & No-filter  & .6625 & .4334 \\
228	     & Binary     & $\mathbf{.6702}$ & $\mathbf{.4480}$ \\
229	     & Graduated  & .6640 & .4334 \\
230	\midrule
231	50\% & No-filter  & .6582 & .4300 \\
232	     & Binary     & $\mathbf{.6700}$ & $\mathbf{.4505}$ \\
233	     & Graduated  & .6606 & .4292 \\
234	\midrule
235	100\% & No-filter & .6217 & .3891 \\
236	      & Binary    & \multicolumn{2}{c}{\emph{N/A (full removal)}} \\
237	      & Graduated & .6215 & .3933 \\
238	\bottomrule
239	\end{tabular}
240	\end{table}
241	
242	\subsection{Feature Subset Stability}
243	\label{sec:feature_subset}
244	
245	To test whether $\Kempirical{=}2$ depends on the specific 15D feature combination, we evaluate random feature subsets of varying size on Pythia-1.4B prompt-chain data (Table~\ref{tab:feature_subset}).
246	
247	\begin{table}[htbp]
248	\centering
249	\small
250	\caption{1v2 $\auc$ by feature subset size (Pythia-1.4B). $\Kempirical{=}2$ ($\auc > \theta{=}0.60$) is robust at $\geq$8 features.}
251	\label{tab:feature_subset}
252	\begin{tabular}{lcccc}
253	\toprule
254	\textbf{Subset} & \textbf{Tested} & \textbf{Pass} & \textbf{Min $\auc$} & \textbf{Mean $\auc$} \\
255	\midrule
256	15D (full) & 1 & 1 & 0.6262 & 0.6262 \\
257	10D        & 5 & 5 & 0.6153 & 0.6191 \\
258	8D         & 5 & 5 & 0.6056 & 0.6159 \\
259	5D         & 5 & 2 & 0.5856 & 0.5998 \\
260	3D (top-3) & 1 & 0 & 0.5871 & 0.5871 \\
261	\bottomrule
262	\end{tabular}
263	\end{table}
264	
265	$\Kempirical{=}2$ holds for all subsets of size $\geq$8 (10/10 pass, min $\auc = 0.6056$), becomes fragile at 5D (2/5 pass), and fails at 3D (top-3 surprisal features alone: $\auc = 0.5871 < \theta$).
266	The boundary does not depend on any specific feature combination but requires sufficient dimensionality ($\geq$8) to capture the multi-faceted distributional shift between generations 1 and 2.
267	
268	\subsection{self\_BLEU Feature Independence}
269	\label{sec:selfbleu_ablation}
270	
271	To verify that $\Kempirical$ does not depend on the self\_BLEU feature (which may reflect stylistic repetition rather than depth-correlated degradation), we compare 15D and 14D (self\_BLEU removed) classifiers across four model configurations (Table~\ref{tab:selfbleu_ablation}).
272	
273	\begin{table}[htbp]
274	\centering
275	\small
276	\caption{15D vs.\ 14D (self\_BLEU removed) 1v2 $\auc$ with bootstrap 95\% CIs. Removing self\_BLEU does not change $\Kempirical$ for any configuration. Maximum $|\Delta\auc| = 0.0031$, within bootstrap CI width (${\sim}0.018$).}
277	\label{tab:selfbleu_ablation}
278	\resizebox{\columnwidth}{!}{%
279	\begin{tabular}{lcccc}
280	\toprule
281	\textbf{Model} & $\Kempirical$ & \textbf{15D $\auc$ [CI]} & \textbf{14D $\auc$ [CI]} & $\Delta$ \\
282	\midrule
283	Qwen-base   & 2/2 & $.6288$ $[.620,\,.638]$ & $.6258$ $[.616,\,.635]$ & $-.0031$ \\
284	Pythia-1.4B  & 2/2 & $.8840$ $[.878,\,.890]$ & $.8830$ $[.876,\,.889]$ & $-.0010$ \\
285	LLaMA-8B     & 2/2 & $.6075$ $[.598,\,.617]$ & $.6074$ $[.598,\,.617]$ & $-.0001$ \\
286	Mistral-7B   & 1/1 & $.5902$ $[.580,\,.600]$ & $.5903$ $[.580,\,.600]$ & $+.0002$ \\
287	\bottomrule
288	\end{tabular}}
289	\end{table}
290	
291	All four configurations preserve their $\Kempirical$ under 14D, with negligible AUC change ($|\Delta| \leq 0.003$).
292	The self\_BLEU feature contributes minimally to the depth boundary; $\Kempirical{=}2$ is driven by surprisal and entropy features rather than lexical repetition statistics.
293	
294	\subsection{Wikipedia Domain: Scorer Confound Resolution}
295	\label{sec:wiki_domain}
296	
297	Under same-family scoring (Qwen-1.5B scorer), Wikipedia $\Kempirical$ appeared to exhibit model-family dependence: Qwen generators (1.5B and 7B) yielded $\Kempirical{=}2$, while all four non-Qwen models yielded $\Kempirical{=}1$ (Table~\ref{tab:wiki_domain}).
298	A scorer confound ablation resolves this apparent split.
299	Rescoring the same Qwen-7B Wikipedia text with Pythia-1.4B reduces 1v2 $\auc$ from $0.611$ to $0.587$ ($\Delta = -2.4$\,pp), dropping $\Kempirical$ from 2 to 1.
300	With the scorer confound controlled, all six models yield $\Kempirical{=}1$ on Wikipedia, and the domain ordering simplifies to: arXiv ($\Kempirical{=}3$) $>$ C4 ($\Kempirical{=}2$) $>$ Wikipedia ($\Kempirical{=}1$).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a09dfb67-fd0c-4bce-bbb5-8fac95aa0d06",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "2ff0b7f8-8a01-4125-b843-289caea73ad1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
      "content": "\\section{Extended Analysis and Limitations}\n\\label{sec:extended_discussion}\n\nThis section provides supporting tables for cross-scorer validation (Tables~\\ref{tab:crossscorer}--\\ref{tab:anova_crossscorer}), followed by extended limitations, ablation studies, and domain-specific analyses.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Cross-scorer validation on Qwen-generated text. Alternative scorers (Pythia-1.4B, OLMo-1B) preserve feature ranking ($\\rho > 0.90$) and rewrite-mode $\\Kempirical = 2$, but reduce continuation-mode $\\Kempirical$ from 2 to 1.}\n\\label{tab:crossscorer}\n\\resizebox{\\columnwidth}{!}{\\input{tables/tab_crossscorer}}\n\\end{table}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Three-way ANOVA (Generator $\\times$ Scorer $\\times$ Depth-Pair) on per-fold pairwise $\\auc$ values (Type~II SS). DV = per-fold AUC; $N{=}300$ (12 cells $\\times$ 5 folds $\\times$ 5 depth-pairs; 3 generators $\\times$ 4 scorers). Scorer is statistically significant ($p < .001$) but has a small effect size ($\\eta^2_p = 0.19$) relative to Depth-Pair ($\\eta^2_p = 1.00$) and Generator ($\\eta^2_p = 0.89$), indicating that scorer choice has a detectable but practically minor influence on depth discrimination (Scorer $\\eta^2_p$ is approximately 5$\\times$ smaller than Generator and dwarfed by Depth-Pair). Per-fold AUC values within the same generator share seed documents across folds and are not fully independent; we therefore rely on effect-size ratios rather than $p$-values for interpretation.}\n\\label{tab:anova_crossscorer}\n\\begin{tabular}{lrrrr}\n\\toprule\n\\textbf{Source} & \\textbf{df} & $F$ & $p$ & $\\eta^2_p$ \\\\\n\\midrule\nGenerator     & 2  & 926.8  & ${<}.001$  & .885 \\\\\nScorer        & 3  & 19.02  & ${<}.001$  & .192 \\\\\nDepth-Pair    & 4  & 24736  & ${<}.001$  & .998 \\\\\nGen$\\times$Scorer & 6 & 8.16 & ${<}.001$ & .170 \\\\\nGen$\\times$Depth  & 8 & 993.7 & ${<}.001$ & .971 \\\\\nScorer$\\times$Depth & 12 & 2.45 & .005 & .109 \\\\\nResidual      & 240 & & & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Extended Limitations}\n\\label{sec:extended_limitations}\n\n\\emph{Prompt-chain versus retrain-chain.}\nQwen2.5-1.5B and Pythia-1.4B yield $\\Kempirical{=}7$ under retrain-chain LoRA fine-tuning (Table~\\ref{tab:retrain_ci}), extending detectable depth by 5 additional generations beyond prompt-chain $\\Kempirical{=}2$.\nOLMo-1B reaches $\\Kempirical{\\geq}4$ (3v4 $\\auc = 0.682$, margin 8\\,pp above $\\theta$; deeper pairs pending), confirming across three architecture families that retrain-chain $\\Kempirical$ is protocol-determined.\nCumulative model-adaptation artifacts (vocabulary narrowing, repetition bias) make each retrained generation highly distinguishable.\nThe two models exhibit different decay profiles: Pythia achieves higher early-pair AUC (1v2: 0.947 vs.\\ 0.897) but drops more steeply at deeper pairs (4v5: 0.691 vs.\\ 0.746), yet both converge to $\\Kempirical{=}7$ (6v7: Qwen 0.641, Pythia 0.634; both CI lower bounds $> \\theta$).\nThis convergence despite differences in effective LoRA adaptation capacity (Pythia uses fused QKV attention with rank-16 vs.\\ Qwen's separate Q/K/V projections) indicates robustness to LoRA parameterization.\nThe extended discriminability under retraining aligns with theoretical analyses of iterative retraining instability on synthetic data~\\cite{bertrand2024stability, gerstgrasser2024model}, where each retraining cycle amplifies distributional artifacts beyond the text-intrinsic degradation observed in prompt-chains.\nExtrapolating yields 7v8 $\\approx 0.57 < \\theta$ for both models. This places $\\Kempirical{=}7$ near the ceiling for retrain-chains.\nPrompt-chain $\\Kempirical$ represents the operationally relevant boundary for data curation (text-intrinsic information loss); retrain-chain $\\Kempirical$ represents the upper bound achievable via model archaeology (known training pipeline).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Retrain-chain pairwise $\\auc$ with 5-fold CV 95\\% CIs. Both models yield $\\Kempirical{=}7$; all CI lower bounds $> \\theta{=}0.60$. Retrain-chain CIs use fold-level estimates (Section~\\ref{sec:retrain_ci_note}).}\n\\label{tab:retrain_ci}\n\\begin{tabular}{lcccc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{Qwen-1.5B}} & \\multicolumn{2}{c}{\\textbf{Pythia-1.4B}} \\\\\n\\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\n\\textbf{Pair} & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI \\\\\n\\midrule\n0v1 & 0.9837 & $[.982,\\,.985]$ & 0.9844 & $[.983,\\,.986]$ \\\\\n1v2 & 0.8971 & $[.895,\\,.899]$ & 0.9470 & $[.942,\\,.952]$ \\\\\n2v3 & 0.8098 & $[.805,\\,.814]$ & 0.8891 & $[.882,\\,.896]$ \\\\\n3v4 & 0.7600 & $[.753,\\,.767]$ & 0.7999 & $[.795,\\,.805]$ \\\\\n4v5 & 0.7459 & $[.738,\\,.754]$ & 0.6907 & $[.688,\\,.693]$ \\\\\n5v6 & 0.7017 & $[.696,\\,.708]$ & 0.6497 & $[.643,\\,.657]$ \\\\\n6v7 & 0.6410 & $[.638,\\,.645]$ & 0.6340 & $[.628,\\,.641]$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{CI methodology note.}\n\\label{sec:retrain_ci_note}\nThe main pipeline reports bootstrap 95\\% CIs (1{,}000 or 10{,}000 resamples), which are valid because each bootstrap sample preserves the GroupKFold document structure: resampling operates on documents, and all depths of a given document remain together.\nIn the retrain-chain setting, each generation's training corpus is the \\emph{output} of the previous generation's fine-tuned model. This creates inter-generation dependencies that standard bootstrap resampling cannot preserve, and naive resampling would inflate AUC estimates.\nRetrain-chain produces only $K{=}5$ independent training runs (one per fold), precluding meaningful document-level bootstrap resampling.\nWe therefore report fold-based 95\\% CIs, computed as $\\bar{x} \\pm t_{0.025,\\,K{-}1} \\cdot s / \\sqrt{K}$ from the $K{=}5$ GroupKFold AUC values ($t_{0.025,4} = 2.776$); the $t$-distribution provides conservative estimation appropriate for this small-sample regime.\n\n\\emph{Threshold sensitivity.}\nTable~\\ref{tab:theta_sensitivity} reports $\\Kempirical$ across $\\theta \\in [0.55, 0.70]$ for representative configurations including arXiv and cross-scorer conditions.\nQwen-continuation's 1v2 CI lower bound exceeds $\\theta$ by only 0.2\\,pp; all ten boundary comparisons yield permutation $p < 0.001$.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{$\\Kempirical$ as a function of $\\theta$ across conditions. The \\textbf{domain ordering} (arXiv $>$ C4 $\\geq$ cross-scorer) is preserved across all $\\theta$ values; absolute $\\Kempirical$ shifts with $\\theta$ but the hierarchy is invariant. The headline result (C4 $\\Kempirical{=}2$, arXiv $\\Kempirical{=}3$) holds for $\\theta \\in [0.575, 0.625]$.}\n\\label{tab:theta_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccccc}\n\\toprule\n\\textbf{Condition} & \\textbf{Config} & $\\theta{=}0.55$ & $\\theta{=}0.575$ & $\\theta{=}0.60$ & $\\theta{=}0.625$ & $\\theta{=}0.65$ & $\\theta{=}0.70$ \\\\\n\\midrule\nC4 (web) & Qwen-rw      & 3 & 3 & 2 & 2 & 2 & 1 \\\\\nC4 (web) & Pythia       & 2 & 2 & 2 & 2 & 1 & 1 \\\\\nC4 (web) & OLMo         & 2 & 2 & 2 & 1 & 1 & 1 \\\\\nC4 (web) & Qwen-cont    & 2 & 2 & 2 & 2 & 1 & 1 \\\\\nC4 (web) & Qwen-7B      & 2 & 2 & 2 & 2 & 1 & 1 \\\\\nC4 (web) & Mistral-7B   & 2 & 2 & 1 & 1 & 1 & 1 \\\\\n\\midrule\narXiv    & Qwen-1.5B-base (cont.) & 3 & 3 & 3 & 3 & 2 & 2 \\\\\narXiv    & Pythia-1.4B (cont.)    & 3 & 3 & 3 & 3 & 2 & 2 \\\\\n\\midrule\nCross-scorer & Qwen-cont/Pythia-scored & 2 & $\\approx$2 & 1 & 1 & 1 & 1 \\\\\nCross-scorer & Qwen-cont/OLMo-scored   & 2 & $\\approx$1 & 1 & 1 & 1 & 1 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[htbp]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_theta_sensitivity.pdf}\n\\caption{$\\Kempirical$ as a function of $\\theta$ across all model $\\times$ domain configurations (three panels: C4, arXiv, Wikipedia). The domain ordering (Wikipedia $\\Kempirical{\\leq}1$ $<$ C4 $\\Kempirical{\\leq}2$ $<$ arXiv $\\Kempirical{\\leq}3$) is preserved across the full $\\theta \\in [0.55, 0.70]$ range. Within each domain, inter-model variation is small relative to inter-domain differences. Source domain rather than model identity governs $\\Kempirical$.}\n\\label{fig:theta_sensitivity}\n\\end{figure}\n\n\\emph{Structural confound: token length.}\nIn continuation mode the generation prompt is discarded, so all depths $\\geq 1$ consist entirely of machine-generated tokens and the 1v2 boundary compares texts differing only in conditioning context (human-authored vs.\\ machine-generated prompt), not structural composition.\nDepth~0 texts average ${\\sim}$191 subword tokens (C4 truncation), while depth~1+ texts average 193--256 tokens depending on model (Table~\\ref{tab:token_length}).\nThis asymmetry is directionally opposite to a length-inflation confound: shorter depth-0 texts provide less feature-extraction context, making 0v1 discrimination harder, not easier.\nWithin depths 1--5, mean token counts are stable (within-model range $\\leq$ 4 tokens for all configurations except Qwen-continuation at 6 tokens), so the pairwise comparisons underlying $\\Kempirical{=}2$ are unaffected by length.\nEOS truncation rates are similarly depth-stable within each model: Qwen-rewrite 7--11\\%, Pythia 34--36\\%, OLMo $<$1\\%, Qwen-continuation 17--20\\%, Qwen-7B 45--47\\%.\nModels with the highest truncation (Pythia, Qwen-7B) still yield $\\Kempirical{=}2$ with the same step-function AUC decay pattern as low-truncation models (Table~\\ref{tab:kstar_ci}), EOS truncation therefore does not drive the boundary.\n\n\\emph{Graduated filtering.}\nAll $\\alpha$ values (0.1--0.9) underperform binary-ours on MMLU ($\\alpha{=}0.1$: 0.5873; $\\alpha{=}0.9$: 0.5892 vs.\\ 0.5941); at $\\alpha{=}0.9$, HellaSwag matches exactly (0.6701).\nBinary-ours significantly outperforms all alternatives on MMLU ($p_{\\text{corr}} \\leq 0.021$); Graduated$_{0.9}$ is indistinguishable on HellaSwag ($p = 1.00$) but worse on MMLU ($p_{\\text{corr}} = 0.011$).\n\\label{tab:pairwise_significance}\n\n\\subsection{Dose-Response: Contamination Ratio Effect}\n\\label{sec:dose_response}\n\nThe main filtering experiments (Section~\\ref{sec:filtering}) use 100\\% synthetic data to maximize effect size.\nTo characterize behavior at lower contamination ratios, we mix synthetic depths 1--5 with clean C4 at 10\\%, 30\\%, and 50\\% contamination (Qwen-1.5B continuation, 5 seeds each; Table~\\ref{tab:dose_response}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{MMLU and HellaSwag by contamination ratio and filtering strategy (5 seeds, mean $\\pm$ std). Base model MMLU: 0.6018. Binary filtering retains a significant advantage on HellaSwag across all ratios ($p \\leq 0.004$, Holm-Bonferroni corrected).}\n\\label{tab:dose_response}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{10\\%}} & \\multicolumn{2}{c}{\\textbf{30\\%}} & \\multicolumn{2}{c}{\\textbf{50\\%}} \\\\\n\\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\\cmidrule(lr){6-7}\n\\textbf{Strategy} & MMLU & HellaSwag & MMLU & HellaSwag & MMLU & HellaSwag \\\\\n\\midrule\nNo-filter   & $.6058{\\pm}.0002$ & $.6689{\\pm}.0006$ & $.6069{\\pm}.0007$ & $.6664{\\pm}.0018$ & $.6063{\\pm}.0012$ & $.6680{\\pm}.0005$ \\\\\nBinary-ours & $\\mathbf{.6079{\\pm}.0004}$ & $\\mathbf{.6727{\\pm}.0007}$ & $\\mathbf{.6082{\\pm}.0011}$ & $\\mathbf{.6725{\\pm}.0006}$ & $\\mathbf{.6088{\\pm}.0009}$ & $\\mathbf{.6731{\\pm}.0004}$ \\\\\nGraduated   & $.6066{\\pm}.0010$ & $.6700{\\pm}.0014$ & $.6072{\\pm}.0008$ & $.6665{\\pm}.0012$ & $.6062{\\pm}.0008$ & $.6679{\\pm}.0001$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nAt all tested ratios (10--50\\%), no-filter MMLU remains above the base model (0.6018), synthetic data at these proportions is therefore net-beneficial rather than harmful.\nBinary filtering consistently improves over no-filter, with HellaSwag differences significant across all ratios ($p \\leq 0.004$, Holm-Bonferroni corrected).\nMMLU differences are smaller and significant only at 10\\% after correction ($p = 0.001$).\nGraduated weighting is indistinguishable from no-filter at all ratios (MMLU $p \\geq 0.27$; HellaSwag $p \\geq 0.06$), depth assignments beyond $\\Kempirical$ therefore inject noise regardless of contamination severity.\nEffect sizes diminish 3--6$\\times$ relative to the 100\\% setting (Section~\\ref{sec:filtering}), but the strategy ordering (binary $>$ graduated $\\approx$ no-filter) is preserved.\n\n\\subsection{Cross-Model Filtering Replication}\n\\label{sec:pythia_filtering}\n\nTo test whether $\\Kempirical{=}2$ correctly predicts optimal curation granularity across architectures, we replicate the filtering experiment on Pythia-1.4B (LoRA rank 8, nucleus $p{=}0.9$, $T{=}1.0$, 3 seeds; Table~\\ref{tab:pythia_filtering}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Pythia-1.4B filtering replication (3 seeds, mean $\\pm$ std). Pythia-1.4B MMLU $\\approx$ random chance (25\\%), yielding low signal-to-noise; benchmark coverage is limited to 2 benchmarks (vs.\\ 5 for Qwen) due to model capacity. Filtering preserves harmlessness and the graduated $\\approx$ no-filter pattern holds across model families.}\n\\label{tab:pythia_filtering}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Strategy} & \\textbf{MMLU} & \\textbf{HellaSwag} \\\\\n\\midrule\nNo-filter & $.2568{\\pm}.0012$ & $.5250{\\pm}.0008$ \\\\\nBinary-ours & $\\mathbf{.2585{\\pm}.0004}$ & $.5251{\\pm}.0001$ \\\\\nGraduated$_{0.9}$ & $.2561{\\pm}.0009$ & $\\mathbf{.5253{\\pm}.0007}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nGraduated filtering performs comparably to no filtering across both benchmarks, consistent with the $\\Kempirical{=}2$ pattern observed on Qwen (Section~\\ref{sec:filtering}).\nThe near-chance MMLU baseline (25\\%) limits signal-to-noise; the key finding is that filtering remains harmless (no degradation) and the graduated $\\approx$ no-filter pattern generalizes across model families, validating $\\Kempirical{=}2$ as cross-architecture guidance.\n\n\\subsection{DeBERTa vs.\\ OBD Filtering Comparison}\n\\label{sec:deberta_filtering}\n\nTo test whether DeBERTa's higher $\\Kempirical$ translates into better downstream curation, we compare filtering strategies using DeBERTa-based ($\\Kempirical{=}4$) and OBD-based ($\\Kempirical{=}2$) depth classifiers on Qwen-1.5B C4 generations (Table~\\ref{tab:deberta_filtering}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{DeBERTa vs.\\ OBD filtering on C4 (Qwen-1.5B, single seed). OBD binary ($\\Kempirical{=}2$) matches or exceeds DeBERTa binary ($\\Kempirical{=}4$) on all three benchmarks; DeBERTa's higher $\\Kempirical$ does not yield better filtering.}\n\\label{tab:deberta_filtering}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Strategy} & \\textbf{MMLU} & \\textbf{HellaSwag} & \\textbf{ARC-C} \\\\\n\\midrule\nNo-filter           & .5895 & .6591 & .4352 \\\\\nOBD binary (15D)    & $\\mathbf{.5880}$ & $\\mathbf{.6599}$ & $\\mathbf{.4522}$ \\\\\nDeBERTa binary      & .5870 & .6593 & .4471 \\\\\nDeBERTa graduated   & .5884 & .6586 & .4420 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOBD binary achieves the highest HellaSwag and ARC-C scores despite using only 15 statistical features and a lower $\\Kempirical$ threshold.\nDeBERTa's richer representations and higher $\\Kempirical{=}4$ do not translate into better filtering performance on web text, consistent with the representation-independent boundary at $\\Kempirical{=}2$ (Section~\\ref{sec:neural_probe}): the additional depth signal recovered by DeBERTa (depths 3--4) carries insufficient distributional information to improve curation.\nThe 15D OBD lower bound is practically sufficient for web text corpus filtering.\n\n\\subsection{Contamination Rate Sensitivity}\n\\label{sec:rate_sweep}\n\nTo characterize filtering performance across contamination severities, we vary the synthetic proportion from 10\\% to 100\\% (single seed, Qwen-1.5B LoRA; Table~\\ref{tab:rate_sweep}).\nBinary filtering advantage on HellaSwag increases monotonically with contamination rate ($\\Delta = +0.57$\\,pp at 10\\%, $+0.77$\\,pp at 30\\%, $+1.18$\\,pp at 50\\%), while graduated filtering remains comparable to no filtering across all rates (max $|\\Delta| \\leq 0.20$\\,pp on HellaSwag, $\\leq 0.42$\\,pp on ARC-C), consistent with $\\Kempirical{=}2$: depth-weighted strategies lack discriminative signal beyond the boundary.\nAt 100\\% synthetic contamination, binary filtering removes the entire corpus; real-world corpora contain a non-trivial human-authored fraction, making this boundary case practically irrelevant.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Contamination rate sensitivity analysis (single seed, Qwen-1.5B LoRA). Binary filtering advantage scales with contamination rate on HellaSwag and ARC-Challenge. Graduated filtering performs comparably to no filtering across all rates. MMLU differences ${<}\\,0.5$\\,pp across all conditions (omitted). At 100\\%, binary filtering removes the entire corpus (N/A).}\n\\label{tab:rate_sweep}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Rate} & \\textbf{Strategy} & \\textbf{HellaSwag} & \\textbf{ARC-C} \\\\\n\\midrule\n10\\% & No-filter  & .6652 & .4471 \\\\\n     & Binary     & $\\mathbf{.6709}$ & $\\mathbf{.4462}$ \\\\\n     & Graduated  & .6672 & .4428 \\\\\n\\midrule\n30\\% & No-filter  & .6625 & .4334 \\\\\n     & Binary     & $\\mathbf{.6702}$ & $\\mathbf{.4480}$ \\\\\n     & Graduated  & .6640 & .4334 \\\\\n\\midrule\n50\\% & No-filter  & .6582 & .4300 \\\\\n     & Binary     & $\\mathbf{.6700}$ & $\\mathbf{.4505}$ \\\\\n     & Graduated  & .6606 & .4292 \\\\\n\\midrule\n100\\% & No-filter & .6217 & .3891 \\\\\n      & Binary    & \\multicolumn{2}{c}{\\emph{N/A (full removal)}} \\\\\n      & Graduated & .6215 & .3933 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Feature Subset Stability}\n\\label{sec:feature_subset}\n\nTo test whether $\\Kempirical{=}2$ depends on the specific 15D feature combination, we evaluate random feature subsets of varying size on Pythia-1.4B prompt-chain data (Table~\\ref{tab:feature_subset}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{1v2 $\\auc$ by feature subset size (Pythia-1.4B). $\\Kempirical{=}2$ ($\\auc > \\theta{=}0.60$) is robust at $\\geq$8 features.}\n\\label{tab:feature_subset}\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Subset} & \\textbf{Tested} & \\textbf{Pass} & \\textbf{Min $\\auc$} & \\textbf{Mean $\\auc$} \\\\\n\\midrule\n15D (full) & 1 & 1 & 0.6262 & 0.6262 \\\\\n10D        & 5 & 5 & 0.6153 & 0.6191 \\\\\n8D         & 5 & 5 & 0.6056 & 0.6159 \\\\\n5D         & 5 & 2 & 0.5856 & 0.5998 \\\\\n3D (top-3) & 1 & 0 & 0.5871 & 0.5871 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n$\\Kempirical{=}2$ holds for all subsets of size $\\geq$8 (10/10 pass, min $\\auc = 0.6056$), becomes fragile at 5D (2/5 pass), and fails at 3D (top-3 surprisal features alone: $\\auc = 0.5871 < \\theta$).\nThe boundary does not depend on any specific feature combination but requires sufficient dimensionality ($\\geq$8) to capture the multi-faceted distributional shift between generations 1 and 2.\n\n\\subsection{self\\_BLEU Feature Independence}\n\\label{sec:selfbleu_ablation}\n\nTo verify that $\\Kempirical$ does not depend on the self\\_BLEU feature (which may reflect stylistic repetition rather than depth-correlated degradation), we compare 15D and 14D (self\\_BLEU removed) classifiers across four model configurations (Table~\\ref{tab:selfbleu_ablation}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{15D vs.\\ 14D (self\\_BLEU removed) 1v2 $\\auc$ with bootstrap 95\\% CIs. Removing self\\_BLEU does not change $\\Kempirical$ for any configuration. Maximum $|\\Delta\\auc| = 0.0031$, within bootstrap CI width (${\\sim}0.018$).}\n\\label{tab:selfbleu_ablation}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & $\\Kempirical$ & \\textbf{15D $\\auc$ [CI]} & \\textbf{14D $\\auc$ [CI]} & $\\Delta$ \\\\\n\\midrule\nQwen-base   & 2/2 & $.6288$ $[.620,\\,.638]$ & $.6258$ $[.616,\\,.635]$ & $-.0031$ \\\\\nPythia-1.4B  & 2/2 & $.8840$ $[.878,\\,.890]$ & $.8830$ $[.876,\\,.889]$ & $-.0010$ \\\\\nLLaMA-8B     & 2/2 & $.6075$ $[.598,\\,.617]$ & $.6074$ $[.598,\\,.617]$ & $-.0001$ \\\\\nMistral-7B   & 1/1 & $.5902$ $[.580,\\,.600]$ & $.5903$ $[.580,\\,.600]$ & $+.0002$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nAll four configurations preserve their $\\Kempirical$ under 14D, with negligible AUC change ($|\\Delta| \\leq 0.003$).\nThe self\\_BLEU feature contributes minimally to the depth boundary; $\\Kempirical{=}2$ is driven by surprisal and entropy features rather than lexical repetition statistics.\n\n\\subsection{Wikipedia Domain: Scorer Confound Resolution}\n\\label{sec:wiki_domain}\n\nUnder same-family scoring (Qwen-1.5B scorer), Wikipedia $\\Kempirical$ appeared to exhibit model-family dependence: Qwen generators (1.5B and 7B) yielded $\\Kempirical{=}2$, while all four non-Qwen models yielded $\\Kempirical{=}1$ (Table~\\ref{tab:wiki_domain}).\nA scorer confound ablation resolves this apparent split.\nRescoring the same Qwen-7B Wikipedia text with Pythia-1.4B reduces 1v2 $\\auc$ from $0.611$ to $0.587$ ($\\Delta = -2.4$\\,pp), dropping $\\Kempirical$ from 2 to 1.\nWith the scorer confound controlled, all six models yield $\\Kempirical{=}1$ on Wikipedia, and the domain ordering simplifies to: arXiv ($\\Kempirical{=}3$) $>$ C4 ($\\Kempirical{=}2$) $>$ Wikipedia ($\\Kempirical{=}1$).",
      "numLines": 300,
      "startLine": 1,
      "totalLines": 1090
    }
  },
  "sourceToolAssistantUUID": "a09dfb67-fd0c-4bce-bbb5-8fac95aa0d06",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 48 · 2026-05-21T06:35:01.840Z_

<details open><summary>🔧 Tool call — Read · `toolu_01275cRcmiLCBSxpjiRtF3zn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_filtering_main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2ff0b7f8-8a01-4125-b843-289caea73ad1",
  "isSidechain": false,
  "requestId": "req_011CbFFQqgWTg5GJGrJkH8kC",
  "type": "assistant",
  "uuid": "60ff7403-1072-41a4-a7d5-fa45f6a62535",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvLQxtAWK5eoqbQjfJjWm6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 30058,
      "cache_read_input_tokens": 50064,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 30058,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 458,
          "cache_read_input_tokens": 50064,
          "cache_creation_input_tokens": 30058,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 30058
          },
          "type": "message"
        }
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

_source line 49 · 2026-05-21T06:35:01.845Z_

<details><summary>↩ Tool result · `toolu_01275cRcmiLCBSxpjiRtF3zn`</summary>

```text
1	\begin{tabular}{lccccc}
2	\toprule
3	\textbf{Strategy} & \textbf{PIQA} & \textbf{TQA} & \textbf{WiGr.} & \textbf{ARC-C} & \textbf{GSM8K} \\
4	\midrule
5	Base model & .7612 & .4659 & .6456 & .5486 & .6224 \\
6	\midrule
7	No filter & \textbf{.7519}$\pm$.0022 & .4246$\pm$.0028 & \textbf{.6485}$\pm$.0032 & \textbf{.5193}$\pm$.0058 & .5666$\pm$.0053 \\
8	Binary ($\Kstar{=}2$) & .7479$\pm$.0016 & \textbf{.4398}$\pm$.0051 & .6406$\pm$.0020 & .5171$\pm$.0038 & \textbf{.5858}$\pm$.0005 \\
9	Graduated & .7510$\pm$.0018 & .4245$\pm$.0027 & .6461$\pm$.0024 & .5190$\pm$.0055 & .5613$\pm$.0038 \\
10	\bottomrule
11	\end{tabular}
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "60ff7403-1072-41a4-a7d5-fa45f6a62535",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "c6afa89f-bf41-481d-bd6f-8bb27afa4db9",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_filtering_main.tex",
      "content": "\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Strategy} & \\textbf{PIQA} & \\textbf{TQA} & \\textbf{WiGr.} & \\textbf{ARC-C} & \\textbf{GSM8K} \\\\\n\\midrule\nBase model & .7612 & .4659 & .6456 & .5486 & .6224 \\\\\n\\midrule\nNo filter & \\textbf{.7519}$\\pm$.0022 & .4246$\\pm$.0028 & \\textbf{.6485}$\\pm$.0032 & \\textbf{.5193}$\\pm$.0058 & .5666$\\pm$.0053 \\\\\nBinary ($\\Kstar{=}2$) & .7479$\\pm$.0016 & \\textbf{.4398}$\\pm$.0051 & .6406$\\pm$.0020 & .5171$\\pm$.0038 & \\textbf{.5858}$\\pm$.0005 \\\\\nGraduated & .7510$\\pm$.0018 & .4245$\\pm$.0027 & .6461$\\pm$.0024 & .5190$\\pm$.0055 & .5613$\\pm$.0038 \\\\\n\\bottomrule\n\\end{tabular}\n",
      "numLines": 12,
      "startLine": 1,
      "totalLines": 12
    }
  },
  "sourceToolAssistantUUID": "60ff7403-1072-41a4-a7d5-fa45f6a62535",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 50 · 2026-05-21T06:35:02.312Z_

<details open><summary>🔧 Tool call — Read · `toolu_01VFyPQyjBd9LzYEgH3ZJiqV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_domain_model_kstar.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c6afa89f-bf41-481d-bd6f-8bb27afa4db9",
  "isSidechain": false,
  "requestId": "req_011CbFFQqgWTg5GJGrJkH8kC",
  "type": "assistant",
  "uuid": "81b9c3de-fd1a-4203-b1b6-1b9cfa203b7b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvLQxtAWK5eoqbQjfJjWm6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 30058,
      "cache_read_input_tokens": 50064,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 30058,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 458,
          "cache_read_input_tokens": 50064,
          "cache_creation_input_tokens": 30058,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 30058
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-21T06:35:02.318Z_

<details><summary>↩ Tool result · `toolu_01VFyPQyjBd9LzYEgH3ZJiqV`</summary>

```text
1	\begin{table}[t]
2	\centering
3	\caption{Generative depth $K^*$ across domains and models (scorer: Qwen2.5-1.5B, $\theta{=}0.60$). Bold values indicate the dominant mode per domain. $K^*$ is remarkably consistent within each domain: C4 yields $K^*{=}2$, arXiv yields $K^*{=}3$, and Wikipedia yields $K^*{=}1$, confirming that generative depth is domain-dependent and low-bounded.}
4	\label{tab:domain_model_kstar}
5	{\small
6	\begin{tabular}{llccc}
7	\toprule
8	\textbf{Model} & \textbf{Size} & \textbf{C4}~$K^*$ & \textbf{arXiv}~$K^*$ & \textbf{Wiki}~$K^*$ \\
9	\midrule
10	Qwen2.5       & 1.5B & \textbf{2} & \textbf{3} & \textbf{1}\textsuperscript{$\dagger$} \\
11	Qwen2.5       & 7B   & \textbf{2} & \textbf{3} & \textbf{1}\textsuperscript{$\dagger$} \\
12	Pythia        & 1.4B & \textbf{2} & \textbf{3} & \textbf{1} \\
13	LLaMA-3.1    & 8B   & \textbf{2} & \textbf{3} & \textbf{1} \\
14	Mistral       & 7B   & 1\textsuperscript{$\ddagger$} & \textbf{3} & \textbf{1} \\
15	OLMo          & 1B   & \textbf{2} & 1\textsuperscript{$*$} & \textbf{1} \\
16	\midrule
17	\textit{Dominant} & & \textbf{2} & \textbf{3} & \textbf{1} \\
18	\bottomrule
19	\end{tabular}
20	}
21	\vspace{2pt}
22	
23	{\footnotesize
24	\textsuperscript{$\dagger$}Scorer artifact: Qwen-1.5B scorer yields $K^*{=}2$; Pythia scorer yields $K^*{=}1$ (see \S\ref{sec:crossscorer}).\\
25	\textsuperscript{$\ddagger$}Domain-specific one-wash: AUC(1v2)${=}0.594{<}\theta$; arXiv rescues to $K^*{=}3$. Cross-scorer validated: Pythia-1.4B also yields $K^*{=}1$ (AUC${=}0.570$).\\
26	\textsuperscript{$*$}Capacity failure: OLMo-1B generates out-of-domain text on arXiv.
27	}
28	\end{table}
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "81b9c3de-fd1a-4203-b1b6-1b9cfa203b7b",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "6d842331-64c9-4f3c-b218-2d5ee456e86b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_domain_model_kstar.tex",
      "content": "\\begin{table}[t]\n\\centering\n\\caption{Generative depth $K^*$ across domains and models (scorer: Qwen2.5-1.5B, $\\theta{=}0.60$). Bold values indicate the dominant mode per domain. $K^*$ is remarkably consistent within each domain: C4 yields $K^*{=}2$, arXiv yields $K^*{=}3$, and Wikipedia yields $K^*{=}1$, confirming that generative depth is domain-dependent and low-bounded.}\n\\label{tab:domain_model_kstar}\n{\\small\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Model} & \\textbf{Size} & \\textbf{C4}~$K^*$ & \\textbf{arXiv}~$K^*$ & \\textbf{Wiki}~$K^*$ \\\\\n\\midrule\nQwen2.5       & 1.5B & \\textbf{2} & \\textbf{3} & \\textbf{1}\\textsuperscript{$\\dagger$} \\\\\nQwen2.5       & 7B   & \\textbf{2} & \\textbf{3} & \\textbf{1}\\textsuperscript{$\\dagger$} \\\\\nPythia        & 1.4B & \\textbf{2} & \\textbf{3} & \\textbf{1} \\\\\nLLaMA-3.1    & 8B   & \\textbf{2} & \\textbf{3} & \\textbf{1} \\\\\nMistral       & 7B   & 1\\textsuperscript{$\\ddagger$} & \\textbf{3} & \\textbf{1} \\\\\nOLMo          & 1B   & \\textbf{2} & 1\\textsuperscript{$*$} & \\textbf{1} \\\\\n\\midrule\n\\textit{Dominant} & & \\textbf{2} & \\textbf{3} & \\textbf{1} \\\\\n\\bottomrule\n\\end{tabular}\n}\n\\vspace{2pt}\n\n{\\footnotesize\n\\textsuperscript{$\\dagger$}Scorer artifact: Qwen-1.5B scorer yields $K^*{=}2$; Pythia scorer yields $K^*{=}1$ (see \\S\\ref{sec:crossscorer}).\\\\\n\\textsuperscript{$\\ddagger$}Domain-specific one-wash: AUC(1v2)${=}0.594{<}\\theta$; arXiv rescues to $K^*{=}3$. Cross-scorer validated: Pythia-1.4B also yields $K^*{=}1$ (AUC${=}0.570$).\\\\\n\\textsuperscript{$*$}Capacity failure: OLMo-1B generates out-of-domain text on arXiv.\n}\n\\end{table}\n",
      "numLines": 29,
      "startLine": 1,
      "totalLines": 29
    }
  },
  "sourceToolAssistantUUID": "81b9c3de-fd1a-4203-b1b6-1b9cfa203b7b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-21T06:35:02.958Z_

<details open><summary>🔧 Tool call — Read · `toolu_019yKUChbHgowryD2d9WBY16`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/tables/tab_crossscorer.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6d842331-64c9-4f3c-b218-2d5ee456e86b",
  "isSidechain": false,
  "requestId": "req_011CbFFQqgWTg5GJGrJkH8kC",
  "type": "assistant",
  "uuid": "3db4e1a0-8f41-4c69-85dd-98a40426cfb3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvLQxtAWK5eoqbQjfJjWm6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 30058,
      "cache_read_input_tokens": 50064,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 30058,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 458,
          "cache_read_input_tokens": 50064,
          "cache_creation_input_tokens": 30058,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 30058
          },
          "type": "message"
        }
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

_source line 53_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "b4ecc4e0-ffe7-4cf7-8f93-34b0f14be6d7",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 54_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Assistant

_source line 55 · 2026-05-21T06:35:06.759Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read more of the appendix_extended to complete my understanding.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b4ecc4e0-ffe7-4cf7-8f93-34b0f14be6d7",
  "isSidechain": false,
  "requestId": "req_011CbFFRbwYSr1ukBCPPqDPL",
  "type": "assistant",
  "uuid": "373e5712-c215-4419-81da-f4cd8cd9c4f8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016hWvVRE44S78BCh59rZxqu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11029,
      "cache_read_input_tokens": 80122,
      "output_tokens": 173,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11029,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 173,
          "cache_read_input_tokens": 80122,
          "cache_creation_input_tokens": 11029,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11029
          },
          "type": "message"
        }
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

_source line 56 · 2026-05-21T06:35:06.761Z_

继续读取 appendix_extended 剩余部分。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "373e5712-c215-4419-81da-f4cd8cd9c4f8",
  "isSidechain": false,
  "requestId": "req_011CbFFRbwYSr1ukBCPPqDPL",
  "type": "assistant",
  "uuid": "1aedde8c-92a2-4363-906a-27c92a1b7eec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016hWvVRE44S78BCh59rZxqu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11029,
      "cache_read_input_tokens": 80122,
      "output_tokens": 173,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11029,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 173,
          "cache_read_input_tokens": 80122,
          "cache_creation_input_tokens": 11029,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11029
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-21T06:35:08.602Z_

<details open><summary>🔧 Tool call — Read · `toolu_01B3tGGVqCf1szrVoehcEYBP`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
  "offset": 300,
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1aedde8c-92a2-4363-906a-27c92a1b7eec",
  "isSidechain": false,
  "requestId": "req_011CbFFRbwYSr1ukBCPPqDPL",
  "type": "assistant",
  "uuid": "3255c446-da0b-466d-a921-f8ecfa5606a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016hWvVRE44S78BCh59rZxqu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11029,
      "cache_read_input_tokens": 80122,
      "output_tokens": 173,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11029,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 173,
          "cache_read_input_tokens": 80122,
          "cache_creation_input_tokens": 11029,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11029
          },
          "type": "message"
        }
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

_source line 58 · 2026-05-21T06:35:08.610Z_

<details><summary>↩ Tool result · `toolu_01B3tGGVqCf1szrVoehcEYBP`</summary>

```text
300	With the scorer confound controlled, all six models yield $\Kempirical{=}1$ on Wikipedia, and the domain ordering simplifies to: arXiv ($\Kempirical{=}3$) $>$ C4 ($\Kempirical{=}2$) $>$ Wikipedia ($\Kempirical{=}1$).
301	
302	\begin{table}[htbp]
303	\centering
304	\small
305	\caption{Wikipedia pairwise $\auc$ across 6 models. $^\dagger$Qwen rows use same-family scorer (Qwen-1.5B); cross-family scoring (Pythia-1.4B) reduces Qwen-7B to $\Kempirical{=}1$ ($\Delta = -2.4$\,pp), resolving the apparent family split.}
306	\label{tab:wiki_domain}
307	\resizebox{\columnwidth}{!}{%
308	\begin{tabular}{llccccc}
309	\toprule
310	\textbf{Model} & \textbf{Family} & \textbf{0v1} & \textbf{1v2} & \textbf{2v3} & $\Kempirical$ & \textbf{Scorer} \\
311	\midrule
312	Qwen-1.5B (base) & Qwen & ---  & .619 & .550 & 2$^\dagger$ & Qwen-1.5B \\
313	Qwen-1.5B (base) & Qwen & ---  & .599 & ---  & 1 & Pythia-1.4B \\
314	Qwen-7B          & Qwen & .967 & .611 & .556 & 2$^\dagger$ & Qwen-1.5B \\
315	Qwen-7B          & Qwen & ---  & .587 & ---  & 1 & Pythia-1.4B \\
316	\midrule
317	Pythia-1.4B   & non-Qwen & .975 & .585 & .545 & 1 & Qwen-1.5B \\
318	OLMo-1B       & non-Qwen & .993 & .498 & .504 & 1 & Qwen-1.5B \\
319	LLaMA-3.1-8B  & non-Qwen & .932 & .595 & .539 & 1 & Qwen-1.5B \\
320	Mistral-7B    & non-Qwen & .961 & .555 & .524 & 1 & Qwen-1.5B \\
321	\bottomrule
322	\multicolumn{7}{l}{\footnotesize $^\dagger$Same-family scorer; cross-family scoring yields $\Kempirical{=}1$.}
323	\end{tabular}}
324	\end{table}
325	
326	\paragraph{Per-fold transparency.}
327	For Qwen-1.5B, cross-family scoring (Pythia-1.4B) yields $\auc$(1v2) $= 0.5994$, with per-fold values $[0.596, 0.606, 0.600, 0.603, 0.592]$ (2/5 folds marginally above $\theta = 0.60$).
328	The aggregate mean falls below $\theta$, confirming $\Kempirical{=}1$.
329	For Qwen-7B, the corresponding $\auc$ drops further to $0.587$.
330	
331	\paragraph{DeBERTa vs.\ OBD on Wikipedia.}
332	Table~\ref{tab:wiki_deberta_comparison} compares DeBERTa-v3-base and OBD-LightGBM on the same Wikipedia generations.
333	While OBD yields $\Kempirical{=}1$ for all five models (all 1v2 $\auc < \theta$), DeBERTa extends $\Kempirical$ to 3 for four of five configurations: Pythia-1.4B, Qwen-7B, LLaMA-8B, and Mistral-7B all exceed $\theta$ at 2v3.
334	OLMo-1B is the sole exception ($\Kempirical{=}1$ under both classifiers), consistent with its near-total distributional collapse at generation~1 (0v1 JSD $= 0.33$; Section~\ref{sec:wiki_domain}).
335	We attribute this to a capacity$\times$domain interaction: OLMo-1B (1.2B parameters) was trained on Dolma, which includes a large Wikipedia proportion; its generations exhibit unusually high stylistic consistency with the source, leaving minimal residual signal for either classifier beyond the first generation.
336	The domain$\times$classifier interaction is stark: on C4, both classifiers agree on $\Kempirical{=}2$ (Table~\ref{tab:deberta_comparison}), but on Wikipedia, DeBERTa recovers two additional depth levels that 15D statistics miss, confirming that the classifier gap is domain-dependent rather than universal.
337	
338	\begin{table}[htbp]
339	\centering
340	\small
341	\caption{Wikipedia $\Kempirical$: DeBERTa-v3-base vs.\ OBD-LightGBM. DeBERTa extends $\Kempirical$ from 1 to 3 for 4/5 models; OLMo-1B remains at $\Kempirical{=}1$ under both classifiers. OBD values use cross-family scoring (Table~\ref{tab:wiki_domain}).}
342	\label{tab:wiki_deberta_comparison}
343	\resizebox{\columnwidth}{!}{%
344	\begin{tabular}{lcccccc}
345	\toprule
346	& \multicolumn{3}{c}{\textbf{OBD-LightGBM}} & \multicolumn{3}{c}{\textbf{DeBERTa-v3-base}} \\
347	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
348	\textbf{Model} & \textbf{1v2} & \textbf{2v3} & $\Kempirical$ & \textbf{1v2} & \textbf{2v3} & $\Kempirical$ \\
349	\midrule
350	Pythia-1.4B   & .585 & .545 & 1 & ---   & .614 & 3 \\
351	OLMo-1B       & .498 & .504 & 1 & .518  & .512 & 1 \\
352	Qwen-7B       & .587 & .556 & 1 & ---   & .631 & 3 \\
353	LLaMA-3.1-8B  & .595 & .539 & 1 & ---   & .634 & 3 \\
354	Mistral-7B    & .555 & .524 & 1 & ---   & .615 & 3 \\
355	\bottomrule
356	\end{tabular}}
357	\end{table}
358	
359	\paragraph{ArXiv DeBERTa vs.\ OBD.}
360	Table~\ref{tab:deberta_arxiv} compares DeBERTa-v3-base and OBD-LightGBM on arXiv (Qwen-1.5B generations).
361	DeBERTa extends $\Kempirical$ from 3 (OBD) to 4, with the largest gain at 2v3 ($+10.1$\,pp).
362	The 3v4 boundary pair ($\auc = 0.624$, CI $[0.613, 0.635]$) exceeds $\theta$, while 4v5 ($\auc = 0.577$) falls below, establishing the neural classifier ceiling at $\Kempirical{=}4$.
363	
364	\begin{table}[htbp]
365	\centering
366	\small
367	\caption{DeBERTa-v3-base vs.\ OBD on arXiv (Qwen-1.5B). DeBERTa extends $\Kempirical$ from 3 to 4.}
368	\label{tab:deberta_arxiv}
369	\resizebox{\columnwidth}{!}{%
370	\begin{tabular}{lccccc}
371	\toprule
372	& \textbf{0v1} & \textbf{1v2} & \textbf{2v3} & \textbf{3v4} & \textbf{4v5} \\
373	\midrule
374	OBD      & .995 & .858 & .644 & .544 & .530 \\
375	DeBERTa  & 1.000 & .921 & .745 & .624 & .577 \\
376	$\Delta$ & +0.5\,pp & +6.3\,pp & +10.1\,pp & +8.0\,pp & +4.7\,pp \\
377	\bottomrule
378	\end{tabular}}
379	\end{table}
380	
381	\paragraph{C4 1.5B DeBERTa across generation configurations.}
382	Table~\ref{tab:deberta_1b5_configs} reports DeBERTa-v3-base results on C4 at 1.5B scale across three generation configurations.
383	All three yield $\Kempirical{=}2$, with 2v3 $\auc$ ranging from 0.542 (Pythia greedy) to 0.599 (Qwen reward-model sampling), all below $\theta$.
384	Pythia-greedy achieves the highest 1v2 $\auc$ (0.928), reflecting greedy decoding's stronger depth-1 signal, but this does not extend the boundary.
385	
386	\begin{table}[htbp]
387	\centering
388	\small
389	\caption{DeBERTa-v3-base on C4 at 1.5B across three generation configurations. $\Kempirical{=}2$ is consistent regardless of generation mode.}
390	\label{tab:deberta_1b5_configs}
391	\resizebox{\columnwidth}{!}{%
392	\begin{tabular}{lcccccc}
393	\toprule
394	\textbf{Configuration} & \textbf{0v1} & \textbf{1v2} & \textbf{2v3} & \textbf{3v4} & \textbf{4v5} & $\Kempirical$ \\
395	\midrule
396	Qwen-1.5B (RW sampling)  & .992 & .705 & .599 & ---  & ---  & 2 \\
397	Qwen-1.5B (continuation) & .996 & .719 & .595 & ---  & ---  & 2 \\
398	Pythia-1.4B (greedy)      & 1.000 & .928 & .542 & .516 & .510 & 2 \\
399	\bottomrule
400	\end{tabular}}
401	\end{table}
402	
403	\paragraph{DeBERTa cross-transfer on Wikipedia.}
404	Table~\ref{tab:wiki_deberta_transfer} reports the full $5{\times}5$ DeBERTa cross-model transfer matrix on Wikipedia (12 off-diagonal pairs with available data).
405	Cross-transfer generally reduces $\Kempirical$ by approximately one level: in-distribution $\Kempirical{=}3$ models (Pythia, Qwen-7B, LLaMA-8B, Mistral-7B) drop to $\Kempirical{=}2$ in most off-diagonal pairs, indicating that roughly one depth level of discriminability is model-specific.
406	The sole cross-transfer pair preserving $\Kempirical{=}3$ is Pythia$\to$Qwen-7B (2v3 $\auc = 0.610$, CI lower $= 0.602$), suggesting Pythia learns the most transferable depth features.
407	All transfers to OLMo-1B yield $\Kempirical{=}1$, consistent with OLMo's distributional collapse under both classifiers (Table~\ref{tab:wiki_deberta_comparison}).
408	
409	\begin{table}[htbp]
410	\centering
411	\small
412	\caption{DeBERTa cross-model transfer on Wikipedia. Each row is a training model; columns show $\Kempirical$ and boundary $\auc$ when tested on a different model's generations. Cross-transfer drops $\Kempirical$ by ${\sim}1$ level; all X$\to$OLMo pairs yield $\Kempirical{=}1$.}
413	\label{tab:wiki_deberta_transfer}
414	\resizebox{\columnwidth}{!}{%
415	\begin{tabular}{llccc}
416	\toprule
417	\textbf{Train} & \textbf{Test} & \textbf{1v2 $\auc$} & \textbf{2v3 $\auc$} & $\Kempirical$ \\
418	\midrule
419	Pythia    & OLMo      & .487 & .491 & 1 \\
420	Pythia    & Qwen-7B   & .701 & .610 & 3 \\
421	Pythia    & LLaMA-8B  & .699 & .607 & 2 \\
422	Pythia    & Mistral-7B & .693 & .601 & 2 \\
423	\midrule
424	OLMo      & Pythia    & .586 & .525 & 1 \\
425	OLMo      & Qwen-7B   & .633 & .546 & 2 \\
426	OLMo      & LLaMA-8B  & .644 & .568 & 2 \\
427	\midrule
428	LLaMA-8B  & OLMo      & .498 & .489 & 1 \\
429	LLaMA-8B  & Pythia    & .680 & .596 & 2 \\
430	\midrule
431	Qwen-7B   & OLMo      & .492 & .489 & 1 \\
432	Qwen-7B   & Pythia    & .665 & .577 & 2 \\
433	\midrule
434	Mistral-7B & Pythia   & .660 & .575 & 2 \\
435	\bottomrule
436	\end{tabular}}
437	\end{table}
438	
439	\subsection{ArXiv Cross-Scorer Bootstrap CIs}
440	\label{sec:arxiv_crossscorer_ci}
441	
442	\begin{table}[htbp]
443	\centering
444	\small
445	\caption{Bootstrap 95\% CI for arXiv cross-scorer (Pythia-1.4B) 2v3 boundary $\auc$ (10{,}000 resamples). Point estimates classify 3/4 generators as $\Kempirical{=}3$; strict CI lower-bound criterion confirms 2/4.}
446	\label{tab:arxiv_crossscorer_ci}
447	\resizebox{\columnwidth}{!}{%
448	\begin{tabular}{lccc}
449	\toprule
450	\textbf{Generator} & \textbf{2v3 $\auc$} & \textbf{95\% CI} & \textbf{CI lower $> \theta$} \\
451	\midrule
452	Qwen-1.5B    & 0.632 & $[0.617,\,0.646]$ & Yes \\
453	LLaMA-3.1-8B & 0.620 & $[0.605,\,0.636]$ & Yes (0.5\,pp margin) \\
454	Mistral-7B   & 0.608 & $[0.593,\,0.622]$ & No \\
455	Qwen-7B      & 0.599 & $[0.584,\,0.613]$ & No \\
456	\bottomrule
457	\end{tabular}}
458	\end{table}
459	
460	\subsection{Scorer Scale Ablation (1.5B vs.\ 7B)}
461	\label{sec:scorer_scale}
462	
463	\begin{table}[htbp]
464	\centering
465	\small
466	\caption{Scorer scale ablation: Qwen2.5-1.5B vs.\ Qwen2.5-7B as reference scorer. $\Kempirical$ is identical across all tested configurations; boundary-pair $\auc$ shifts are below 1\,pp.}
467	\label{tab:scorer_scale}
468	\resizebox{\columnwidth}{!}{%
469	\begin{tabular}{llccccc}
470	\toprule
471	\textbf{Domain} & \textbf{Generator} & \textbf{Boundary} & $\Kempirical$ \textbf{(1.5B)} & $\Kempirical$ \textbf{(7B)} & \textbf{Boundary $\auc$} & $\Delta$ \\
472	\midrule
473	C4    & Pythia-1.4B  & 1v2 & 2 & 2 & .654 / .654 & $+$0.1\,pp \\
474	arXiv & Pythia-1.4B  & 2v3 & 3 & 3 & .654 / .655 & $+$0.1\,pp \\
475	arXiv & OLMo-1B      & 1v2 & 1 & 1 & .518 / .509 & $-$0.9\,pp \\
476	\bottomrule
477	\end{tabular}}
478	\end{table}
479	
480	\subsection{JSD Decay Analysis}
481	\label{sec:jsd_extended}
482	
483	The token-level JSD between adjacent generations reveals two distinct decay regimes (Figure~\ref{fig:jsd_decay}).
484	For C4 web text, 0v1 JSD exceeds 1v2 by 6--56$\times$ across all 8 models (1B--14B) with $\Kempirical{=}2$ (median cliff ratio ${\sim}$15$\times$), and subsequent pairs converge to a noise floor of ${\sim}$0.003--0.005.
485	Fitting $\jsd(k, k{+}1) \propto e^{-\lambda k}$ yields $\lambda \approx 2.2$--$3.5$ for C4 (mean ${\approx}\,2.9$), consistent with rapid mixing of $G_\delta$ toward its stationary distribution.
486	These decay rates represent qualitative characterizations from 5-point curves rather than precise estimates.
487	The empirical decay rate $\lambda$ is consistent within each domain but varies across domains: C4 yields $\lambda \approx 2.9$, Wikipedia $\lambda \approx 3.1$ (excluding OLMo, whose $\lambda = 6.3$ reflects a capacity-limited collapse: 0v1 $\jsd = 0.169$ with near-complete information loss at the first step, the exponential fit is therefore unreliable), and arXiv $\lambda \approx 1.0$.
488	This cross-model consistency indicates that the contraction rate of $G_\delta$ is governed primarily by the structure of the input domain rather than the model architecture.
489	ArXiv text decays ${\sim}$3$\times$ slower than C4 ($\lambda \approx 1.0$ vs.\ $2.9$), with a correspondingly higher convergence floor (${\sim}$0.007--0.009 vs.\ ${\sim}$0.003--0.004).
490	Formulaic structural features (LaTeX formatting, citation patterns, section templates) degrade more slowly under autoregressive generation and supply persistent depth-distinguishing signal, this accounts for the elevated $\Kempirical{=}3$.
491	The retrain-chain exhibits a fundamentally different profile: $\lambda = 0.285$ with a cliff ratio of only 1.31$\times$ and no sharp drop between adjacent pairs (Figure~\ref{fig:retrain_decay}).
492	This gradual, sustained divergence reflects cumulative model-adaptation artifacts rather than text-intrinsic information loss, further supporting the distinction between prompt-chain and retrain-chain $\Kempirical$ (Appendix~\ref{sec:boundary_extended}).
493	
494	\begin{figure}[htbp]
495	\centering
496	\includegraphics[width=\columnwidth]{figures/fig_retrain_decay.png}
497	\caption{Retrain-chain AUC decay across 7 generation pairs (Qwen2.5-1.5B LoRA). Unlike prompt-chain (sharp cliff at 0v1$\to$1v2), retrain-chain AUC decays gradually from 0.984 to 0.641, with all pairs above $\theta{=}0.60$. Error bars: 95\% CI from 5-fold CV. Dashed line: $\theta{=}0.60$; extrapolated 7v8 $\approx 0.57$ (below $\theta$), suggesting $\Kempirical{=}7$ is near the ceiling.}
498	\label{fig:retrain_decay}
499	\end{figure}
500	
501	\subsection{Boundary Cases and Scale Effect}
502	\label{sec:boundary_extended}
503	
504	Of 9 continuation-mode configurations on C4, 7 yield $\Kempirical{=}2$; Gemma-2-2B and Mistral-7B are competence-limited at $\Kempirical{=}1$ (1v2 $\auc$: 0.598, 0.594 respectively), validating $\theta{=}0.60$ as an effective discriminator (gap: $0.594$--$0.598$ vs.\ $0.611$--$0.654$).
505	Mistral's cross-domain profile reinforces the domain-governed interpretation: despite $\Kempirical{=}1$ on C4 and Wikipedia, it yields $\Kempirical{=}2$ on code and $\Kempirical{=}3$ on arXiv (1v2 $\auc = 0.820$, 2v3 $= 0.628$), and this profile persists under cross-scorer validation (Pythia-1.4B scorer: C4 $\Kempirical{=}1$, arXiv $\Kempirical{=}3$ (2v3 $\auc = 0.608$, CI $[0.593, 0.622]$)), domain lexical diversity can therefore rescue even web-text one-wash generators (Table~\ref{tab:domain_kstar}).
506	Larger models produce more human-like text, reducing 0v1 JSD: 0.16--0.29 at $\leq$1.5B, 0.077--0.13 at 7--14B.
507	However, Qwen-14B still yields $\Kempirical{=}2$ (1v2 $\auc = 0.621$, CI $[0.612, 0.630]$), with 0v1 $\auc = 0.960$ comparable to Qwen-7B ($0.964$), scale in the 1B--14B range therefore does not shift the discrimination boundary.
508	
509	\paragraph{Sample-size control.}
510	As a sample-size control, subsampling C4 to $n{=}2{,}200$ (matching arXiv) yields $\Kempirical{=}1$ (1v2 $\auc = 0.601$, CI $[0.586, 0.616]$).
511	Reduced sample size widens confidence intervals and produces more conservative $\Kempirical$ estimates, arXiv's $\Kempirical{=}3$ at the same sample size therefore reflects genuine domain signal rather than a statistical artifact of smaller training sets.
512	
513	\subsection{LaTeX Markup Ablation (arXiv)}
514	\label{sec:latex_ablation}
515	
516	To disentangle content-level depth signal from formatting artifacts on arXiv, we strip all LaTeX markup (commands, environments, inline math delimiters) and re-extract features from the plain-text residual (Qwen-1.5B continuation, $n{=}2{,}200$; Table~\ref{tab:latex_ablation}).
517	
518	\begin{table}[htbp]
519	\centering
520	\small
521	\caption{arXiv pairwise $\auc$ with and without LaTeX markup (Qwen-1.5B continuation). Removing formatting reduces 2v3 by ${\sim}$1.8\,pp but $\Kempirical$ remains at 3 (CI lower $> \theta$). LaTeX stripping fraction increases with depth (0.6\% at depth 0, 4.6\% at depth 5), deeper generations therefore produce proportionally more formatting tokens.}
522	\label{tab:latex_ablation}
523	\resizebox{\columnwidth}{!}{%
524	\begin{tabular}{lccr}
525	\toprule
526	\textbf{Pair} & \textbf{Original} & \textbf{Stripped} & $\Delta$ \\
527	\midrule
528	0v1 & 0.9946 & 0.9948 & $+$0.0002 \\
529	1v2 & 0.8580 & 0.8297 & $-$0.028 \\
530	2v3 & 0.6427 $[0.628,\,0.658]$ & 0.6248 $[0.610,\,0.640]$ & $-$0.018 \\
531	3v4 & 0.5437 & 0.5468 & $+$0.003 \\
532	\midrule
533	$\Kempirical$ & 3 & 3 & --- \\
534	\bottomrule
535	\end{tabular}}
536	\end{table}
537	
538	Content-level statistical properties (surprisal distribution, vocabulary diversity) account for the large majority of the depth signal; LaTeX formatting contributes a modest but measurable increment (${\sim}$1.8\,pp at the boundary pair).
539	The depth-correlated increase in LaTeX stripping fraction (depth 0: $-$0.6\%, depth 5: $-$4.6\%) indicates that autoregressive generation progressively introduces formatting tokens, consistent with mode-seeking behavior in structured text.
540	
541	\subsection{Statistical Power Analysis}
542	\label{sec:power_curve}
543	
544	To characterize the minimum sample size required for reliable $\Kempirical$ determination, we subsample C4 at $n \in \{500, 1000, 2000, 3000, 4000, 5000\}$ and measure 1v2 AUC stability across 10 resamples per size (Qwen-1.5B-base continuation, 5-fold GroupKFold; Table~\ref{tab:power_curve}, Figure~\ref{fig:power_curve}).
545	
546	\begin{table}[htbp]
547	\centering
548	\small
549	\caption{Subsampling power analysis for $\Kempirical{=}2$ determination (C4, Qwen-1.5B-base, 10 resamples per $n$). Detection probability: fraction of resamples where 1v2 $\auc > \theta{=}0.60$.}
550	\label{tab:power_curve}
551	\begin{tabular}{rccc}
552	\toprule
553	$n$ & \textbf{Mean 1v2 $\auc$} & \textbf{Std} & \textbf{Detection Prob.} \\
554	\midrule
555	500 & 0.581 & 0.018 & 20\% \\
556	1{,}000 & 0.591 & 0.014 & 30\% \\
557	2{,}000 & 0.610 & 0.009 & 100\% \\
558	3{,}000 & 0.617 & 0.005 & 100\% \\
559	4{,}000 & 0.622 & 0.004 & 100\% \\
560	5{,}000 & 0.629 & 0.000 & 100\% \\
561	\bottomrule
562	\end{tabular}
563	\end{table}
564	
565	\begin{figure}[htbp]
566	\centering
567	\includegraphics[width=\columnwidth]{figures/fig_power_curve.png}
568	\caption{$\Kempirical{=}2$ detection rate (left axis, blue) and mean 1v2 $\auc$ (right axis, green) as a function of sample size $n$. Detection rate reaches 100\% at $n{=}2{,}000$; the 80\% power threshold (dotted purple) is crossed between $n{=}1{,}000$ and $n{=}2{,}000$. Error bars: $\pm$1 std over 10 resamples. The dashed red line marks $\theta{=}0.60$.}
569	\label{fig:power_curve}
570	\end{figure}
571	
572	Detection rate jumps from 20\% ($n{=}500$) to 100\% ($n{=}2{,}000$), with the 80\% power threshold crossed near $n{=}1{,}500$.
573	At $n{=}5{,}000$ (the sample size used in all main experiments), variance is zero across resamples, our results are therefore well above the minimum required for reliable boundary estimation.
574	The sharp transition reflects the proximity of the 1v2 AUC to $\theta$: small increases in $n$ reduce variance sufficiently to move all resamples above the threshold.
575	
576	\subsection{Feature Group Ablation}
577	\label{sec:feature_ablation}
578	
579	To assess the relative contribution of each feature group to depth discrimination, we train a plain LightGBM classifier (\texttt{n\_estimators}$=$200, \texttt{max\_depth}$=$6; distinct from the OBD-LightGBM used in Section~\ref{sec:method}) on the 1\,vs.\,2 task using (a) each feature group alone (\emph{single}) and (b) the full 15D set minus one group (\emph{leave-one-out}).
580	Representative models per domain: LLaMA-3.1-8B (C4), Qwen-1.5B continuation (arXiv), and the domain ablation configuration (Wikipedia).
581	
582	\begin{figure}[htbp]
583	\centering
584	\includegraphics[width=\columnwidth]{figures/fig_feature_ablation.pdf}
585	\caption{Feature group ablation heatmap for 1\,vs.\,2 classification AUC. \emph{Left}: single-group performance. \emph{Right}: leave-one-out performance. Surprisal (base) features are the dominant signal on arXiv (single AUC $= 0.809$) but provide only weak marginal signal on C4 and Wikipedia.}
586	\label{fig:feature_ablation}
587	\end{figure}
588	
589	\begin{table}[htbp]
590	\centering
591	\small
592	\caption{Feature group ablation for 1\,vs.\,2 classification (AUC). \textbf{Single}: using only features from one group. \textbf{Leave-one-out}: removing one group from the full 15D feature set. $\Delta$ denotes the AUC drop from the full model. Classifier: plain LightGBM (\texttt{n\_estimators}$=$200, \texttt{max\_depth}$=$6), distinct from the OBD-LightGBM pipeline; AUC values are not directly comparable to Table~\ref{tab:kstar_ci}.}
593	\label{tab:feature_ablation}
594	\resizebox{\columnwidth}{!}{%
595	\begin{tabular}{l ccc ccc}
596	\toprule
597	& \multicolumn{3}{c}{\textbf{Single Group}} & \multicolumn{3}{c}{\textbf{Leave-One-Out ($\Delta$)}} \\
598	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
599	Feature Group & C4 & arXiv & Wiki & C4 & arXiv & Wiki \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3255c446-da0b-466d-a921-f8ecfa5606a3",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "cf1d1f78-513a-4067-865f-216f5e985dc8",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
      "content": "With the scorer confound controlled, all six models yield $\\Kempirical{=}1$ on Wikipedia, and the domain ordering simplifies to: arXiv ($\\Kempirical{=}3$) $>$ C4 ($\\Kempirical{=}2$) $>$ Wikipedia ($\\Kempirical{=}1$).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Wikipedia pairwise $\\auc$ across 6 models. $^\\dagger$Qwen rows use same-family scorer (Qwen-1.5B); cross-family scoring (Pythia-1.4B) reduces Qwen-7B to $\\Kempirical{=}1$ ($\\Delta = -2.4$\\,pp), resolving the apparent family split.}\n\\label{tab:wiki_domain}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{0v1} & \\textbf{1v2} & \\textbf{2v3} & $\\Kempirical$ & \\textbf{Scorer} \\\\\n\\midrule\nQwen-1.5B (base) & Qwen & ---  & .619 & .550 & 2$^\\dagger$ & Qwen-1.5B \\\\\nQwen-1.5B (base) & Qwen & ---  & .599 & ---  & 1 & Pythia-1.4B \\\\\nQwen-7B          & Qwen & .967 & .611 & .556 & 2$^\\dagger$ & Qwen-1.5B \\\\\nQwen-7B          & Qwen & ---  & .587 & ---  & 1 & Pythia-1.4B \\\\\n\\midrule\nPythia-1.4B   & non-Qwen & .975 & .585 & .545 & 1 & Qwen-1.5B \\\\\nOLMo-1B       & non-Qwen & .993 & .498 & .504 & 1 & Qwen-1.5B \\\\\nLLaMA-3.1-8B  & non-Qwen & .932 & .595 & .539 & 1 & Qwen-1.5B \\\\\nMistral-7B    & non-Qwen & .961 & .555 & .524 & 1 & Qwen-1.5B \\\\\n\\bottomrule\n\\multicolumn{7}{l}{\\footnotesize $^\\dagger$Same-family scorer; cross-family scoring yields $\\Kempirical{=}1$.}\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Per-fold transparency.}\nFor Qwen-1.5B, cross-family scoring (Pythia-1.4B) yields $\\auc$(1v2) $= 0.5994$, with per-fold values $[0.596, 0.606, 0.600, 0.603, 0.592]$ (2/5 folds marginally above $\\theta = 0.60$).\nThe aggregate mean falls below $\\theta$, confirming $\\Kempirical{=}1$.\nFor Qwen-7B, the corresponding $\\auc$ drops further to $0.587$.\n\n\\paragraph{DeBERTa vs.\\ OBD on Wikipedia.}\nTable~\\ref{tab:wiki_deberta_comparison} compares DeBERTa-v3-base and OBD-LightGBM on the same Wikipedia generations.\nWhile OBD yields $\\Kempirical{=}1$ for all five models (all 1v2 $\\auc < \\theta$), DeBERTa extends $\\Kempirical$ to 3 for four of five configurations: Pythia-1.4B, Qwen-7B, LLaMA-8B, and Mistral-7B all exceed $\\theta$ at 2v3.\nOLMo-1B is the sole exception ($\\Kempirical{=}1$ under both classifiers), consistent with its near-total distributional collapse at generation~1 (0v1 JSD $= 0.33$; Section~\\ref{sec:wiki_domain}).\nWe attribute this to a capacity$\\times$domain interaction: OLMo-1B (1.2B parameters) was trained on Dolma, which includes a large Wikipedia proportion; its generations exhibit unusually high stylistic consistency with the source, leaving minimal residual signal for either classifier beyond the first generation.\nThe domain$\\times$classifier interaction is stark: on C4, both classifiers agree on $\\Kempirical{=}2$ (Table~\\ref{tab:deberta_comparison}), but on Wikipedia, DeBERTa recovers two additional depth levels that 15D statistics miss, confirming that the classifier gap is domain-dependent rather than universal.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Wikipedia $\\Kempirical$: DeBERTa-v3-base vs.\\ OBD-LightGBM. DeBERTa extends $\\Kempirical$ from 1 to 3 for 4/5 models; OLMo-1B remains at $\\Kempirical{=}1$ under both classifiers. OBD values use cross-family scoring (Table~\\ref{tab:wiki_domain}).}\n\\label{tab:wiki_deberta_comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{OBD-LightGBM}} & \\multicolumn{3}{c}{\\textbf{DeBERTa-v3-base}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Model} & \\textbf{1v2} & \\textbf{2v3} & $\\Kempirical$ & \\textbf{1v2} & \\textbf{2v3} & $\\Kempirical$ \\\\\n\\midrule\nPythia-1.4B   & .585 & .545 & 1 & ---   & .614 & 3 \\\\\nOLMo-1B       & .498 & .504 & 1 & .518  & .512 & 1 \\\\\nQwen-7B       & .587 & .556 & 1 & ---   & .631 & 3 \\\\\nLLaMA-3.1-8B  & .595 & .539 & 1 & ---   & .634 & 3 \\\\\nMistral-7B    & .555 & .524 & 1 & ---   & .615 & 3 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{ArXiv DeBERTa vs.\\ OBD.}\nTable~\\ref{tab:deberta_arxiv} compares DeBERTa-v3-base and OBD-LightGBM on arXiv (Qwen-1.5B generations).\nDeBERTa extends $\\Kempirical$ from 3 (OBD) to 4, with the largest gain at 2v3 ($+10.1$\\,pp).\nThe 3v4 boundary pair ($\\auc = 0.624$, CI $[0.613, 0.635]$) exceeds $\\theta$, while 4v5 ($\\auc = 0.577$) falls below, establishing the neural classifier ceiling at $\\Kempirical{=}4$.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{DeBERTa-v3-base vs.\\ OBD on arXiv (Qwen-1.5B). DeBERTa extends $\\Kempirical$ from 3 to 4.}\n\\label{tab:deberta_arxiv}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n& \\textbf{0v1} & \\textbf{1v2} & \\textbf{2v3} & \\textbf{3v4} & \\textbf{4v5} \\\\\n\\midrule\nOBD      & .995 & .858 & .644 & .544 & .530 \\\\\nDeBERTa  & 1.000 & .921 & .745 & .624 & .577 \\\\\n$\\Delta$ & +0.5\\,pp & +6.3\\,pp & +10.1\\,pp & +8.0\\,pp & +4.7\\,pp \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{C4 1.5B DeBERTa across generation configurations.}\nTable~\\ref{tab:deberta_1b5_configs} reports DeBERTa-v3-base results on C4 at 1.5B scale across three generation configurations.\nAll three yield $\\Kempirical{=}2$, with 2v3 $\\auc$ ranging from 0.542 (Pythia greedy) to 0.599 (Qwen reward-model sampling), all below $\\theta$.\nPythia-greedy achieves the highest 1v2 $\\auc$ (0.928), reflecting greedy decoding's stronger depth-1 signal, but this does not extend the boundary.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{DeBERTa-v3-base on C4 at 1.5B across three generation configurations. $\\Kempirical{=}2$ is consistent regardless of generation mode.}\n\\label{tab:deberta_1b5_configs}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n\\textbf{Configuration} & \\textbf{0v1} & \\textbf{1v2} & \\textbf{2v3} & \\textbf{3v4} & \\textbf{4v5} & $\\Kempirical$ \\\\\n\\midrule\nQwen-1.5B (RW sampling)  & .992 & .705 & .599 & ---  & ---  & 2 \\\\\nQwen-1.5B (continuation) & .996 & .719 & .595 & ---  & ---  & 2 \\\\\nPythia-1.4B (greedy)      & 1.000 & .928 & .542 & .516 & .510 & 2 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{DeBERTa cross-transfer on Wikipedia.}\nTable~\\ref{tab:wiki_deberta_transfer} reports the full $5{\\times}5$ DeBERTa cross-model transfer matrix on Wikipedia (12 off-diagonal pairs with available data).\nCross-transfer generally reduces $\\Kempirical$ by approximately one level: in-distribution $\\Kempirical{=}3$ models (Pythia, Qwen-7B, LLaMA-8B, Mistral-7B) drop to $\\Kempirical{=}2$ in most off-diagonal pairs, indicating that roughly one depth level of discriminability is model-specific.\nThe sole cross-transfer pair preserving $\\Kempirical{=}3$ is Pythia$\\to$Qwen-7B (2v3 $\\auc = 0.610$, CI lower $= 0.602$), suggesting Pythia learns the most transferable depth features.\nAll transfers to OLMo-1B yield $\\Kempirical{=}1$, consistent with OLMo's distributional collapse under both classifiers (Table~\\ref{tab:wiki_deberta_comparison}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{DeBERTa cross-model transfer on Wikipedia. Each row is a training model; columns show $\\Kempirical$ and boundary $\\auc$ when tested on a different model's generations. Cross-transfer drops $\\Kempirical$ by ${\\sim}1$ level; all X$\\to$OLMo pairs yield $\\Kempirical{=}1$.}\n\\label{tab:wiki_deberta_transfer}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Train} & \\textbf{Test} & \\textbf{1v2 $\\auc$} & \\textbf{2v3 $\\auc$} & $\\Kempirical$ \\\\\n\\midrule\nPythia    & OLMo      & .487 & .491 & 1 \\\\\nPythia    & Qwen-7B   & .701 & .610 & 3 \\\\\nPythia    & LLaMA-8B  & .699 & .607 & 2 \\\\\nPythia    & Mistral-7B & .693 & .601 & 2 \\\\\n\\midrule\nOLMo      & Pythia    & .586 & .525 & 1 \\\\\nOLMo      & Qwen-7B   & .633 & .546 & 2 \\\\\nOLMo      & LLaMA-8B  & .644 & .568 & 2 \\\\\n\\midrule\nLLaMA-8B  & OLMo      & .498 & .489 & 1 \\\\\nLLaMA-8B  & Pythia    & .680 & .596 & 2 \\\\\n\\midrule\nQwen-7B   & OLMo      & .492 & .489 & 1 \\\\\nQwen-7B   & Pythia    & .665 & .577 & 2 \\\\\n\\midrule\nMistral-7B & Pythia   & .660 & .575 & 2 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\subsection{ArXiv Cross-Scorer Bootstrap CIs}\n\\label{sec:arxiv_crossscorer_ci}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Bootstrap 95\\% CI for arXiv cross-scorer (Pythia-1.4B) 2v3 boundary $\\auc$ (10{,}000 resamples). Point estimates classify 3/4 generators as $\\Kempirical{=}3$; strict CI lower-bound criterion confirms 2/4.}\n\\label{tab:arxiv_crossscorer_ci}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Generator} & \\textbf{2v3 $\\auc$} & \\textbf{95\\% CI} & \\textbf{CI lower $> \\theta$} \\\\\n\\midrule\nQwen-1.5B    & 0.632 & $[0.617,\\,0.646]$ & Yes \\\\\nLLaMA-3.1-8B & 0.620 & $[0.605,\\,0.636]$ & Yes (0.5\\,pp margin) \\\\\nMistral-7B   & 0.608 & $[0.593,\\,0.622]$ & No \\\\\nQwen-7B      & 0.599 & $[0.584,\\,0.613]$ & No \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\subsection{Scorer Scale Ablation (1.5B vs.\\ 7B)}\n\\label{sec:scorer_scale}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Scorer scale ablation: Qwen2.5-1.5B vs.\\ Qwen2.5-7B as reference scorer. $\\Kempirical$ is identical across all tested configurations; boundary-pair $\\auc$ shifts are below 1\\,pp.}\n\\label{tab:scorer_scale}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Generator} & \\textbf{Boundary} & $\\Kempirical$ \\textbf{(1.5B)} & $\\Kempirical$ \\textbf{(7B)} & \\textbf{Boundary $\\auc$} & $\\Delta$ \\\\\n\\midrule\nC4    & Pythia-1.4B  & 1v2 & 2 & 2 & .654 / .654 & $+$0.1\\,pp \\\\\narXiv & Pythia-1.4B  & 2v3 & 3 & 3 & .654 / .655 & $+$0.1\\,pp \\\\\narXiv & OLMo-1B      & 1v2 & 1 & 1 & .518 / .509 & $-$0.9\\,pp \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\subsection{JSD Decay Analysis}\n\\label{sec:jsd_extended}\n\nThe token-level JSD between adjacent generations reveals two distinct decay regimes (Figure~\\ref{fig:jsd_decay}).\nFor C4 web text, 0v1 JSD exceeds 1v2 by 6--56$\\times$ across all 8 models (1B--14B) with $\\Kempirical{=}2$ (median cliff ratio ${\\sim}$15$\\times$), and subsequent pairs converge to a noise floor of ${\\sim}$0.003--0.005.\nFitting $\\jsd(k, k{+}1) \\propto e^{-\\lambda k}$ yields $\\lambda \\approx 2.2$--$3.5$ for C4 (mean ${\\approx}\\,2.9$), consistent with rapid mixing of $G_\\delta$ toward its stationary distribution.\nThese decay rates represent qualitative characterizations from 5-point curves rather than precise estimates.\nThe empirical decay rate $\\lambda$ is consistent within each domain but varies across domains: C4 yields $\\lambda \\approx 2.9$, Wikipedia $\\lambda \\approx 3.1$ (excluding OLMo, whose $\\lambda = 6.3$ reflects a capacity-limited collapse: 0v1 $\\jsd = 0.169$ with near-complete information loss at the first step, the exponential fit is therefore unreliable), and arXiv $\\lambda \\approx 1.0$.\nThis cross-model consistency indicates that the contraction rate of $G_\\delta$ is governed primarily by the structure of the input domain rather than the model architecture.\nArXiv text decays ${\\sim}$3$\\times$ slower than C4 ($\\lambda \\approx 1.0$ vs.\\ $2.9$), with a correspondingly higher convergence floor (${\\sim}$0.007--0.009 vs.\\ ${\\sim}$0.003--0.004).\nFormulaic structural features (LaTeX formatting, citation patterns, section templates) degrade more slowly under autoregressive generation and supply persistent depth-distinguishing signal, this accounts for the elevated $\\Kempirical{=}3$.\nThe retrain-chain exhibits a fundamentally different profile: $\\lambda = 0.285$ with a cliff ratio of only 1.31$\\times$ and no sharp drop between adjacent pairs (Figure~\\ref{fig:retrain_decay}).\nThis gradual, sustained divergence reflects cumulative model-adaptation artifacts rather than text-intrinsic information loss, further supporting the distinction between prompt-chain and retrain-chain $\\Kempirical$ (Appendix~\\ref{sec:boundary_extended}).\n\n\\begin{figure}[htbp]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_retrain_decay.png}\n\\caption{Retrain-chain AUC decay across 7 generation pairs (Qwen2.5-1.5B LoRA). Unlike prompt-chain (sharp cliff at 0v1$\\to$1v2), retrain-chain AUC decays gradually from 0.984 to 0.641, with all pairs above $\\theta{=}0.60$. Error bars: 95\\% CI from 5-fold CV. Dashed line: $\\theta{=}0.60$; extrapolated 7v8 $\\approx 0.57$ (below $\\theta$), suggesting $\\Kempirical{=}7$ is near the ceiling.}\n\\label{fig:retrain_decay}\n\\end{figure}\n\n\\subsection{Boundary Cases and Scale Effect}\n\\label{sec:boundary_extended}\n\nOf 9 continuation-mode configurations on C4, 7 yield $\\Kempirical{=}2$; Gemma-2-2B and Mistral-7B are competence-limited at $\\Kempirical{=}1$ (1v2 $\\auc$: 0.598, 0.594 respectively), validating $\\theta{=}0.60$ as an effective discriminator (gap: $0.594$--$0.598$ vs.\\ $0.611$--$0.654$).\nMistral's cross-domain profile reinforces the domain-governed interpretation: despite $\\Kempirical{=}1$ on C4 and Wikipedia, it yields $\\Kempirical{=}2$ on code and $\\Kempirical{=}3$ on arXiv (1v2 $\\auc = 0.820$, 2v3 $= 0.628$), and this profile persists under cross-scorer validation (Pythia-1.4B scorer: C4 $\\Kempirical{=}1$, arXiv $\\Kempirical{=}3$ (2v3 $\\auc = 0.608$, CI $[0.593, 0.622]$)), domain lexical diversity can therefore rescue even web-text one-wash generators (Table~\\ref{tab:domain_kstar}).\nLarger models produce more human-like text, reducing 0v1 JSD: 0.16--0.29 at $\\leq$1.5B, 0.077--0.13 at 7--14B.\nHowever, Qwen-14B still yields $\\Kempirical{=}2$ (1v2 $\\auc = 0.621$, CI $[0.612, 0.630]$), with 0v1 $\\auc = 0.960$ comparable to Qwen-7B ($0.964$), scale in the 1B--14B range therefore does not shift the discrimination boundary.\n\n\\paragraph{Sample-size control.}\nAs a sample-size control, subsampling C4 to $n{=}2{,}200$ (matching arXiv) yields $\\Kempirical{=}1$ (1v2 $\\auc = 0.601$, CI $[0.586, 0.616]$).\nReduced sample size widens confidence intervals and produces more conservative $\\Kempirical$ estimates, arXiv's $\\Kempirical{=}3$ at the same sample size therefore reflects genuine domain signal rather than a statistical artifact of smaller training sets.\n\n\\subsection{LaTeX Markup Ablation (arXiv)}\n\\label{sec:latex_ablation}\n\nTo disentangle content-level depth signal from formatting artifacts on arXiv, we strip all LaTeX markup (commands, environments, inline math delimiters) and re-extract features from the plain-text residual (Qwen-1.5B continuation, $n{=}2{,}200$; Table~\\ref{tab:latex_ablation}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{arXiv pairwise $\\auc$ with and without LaTeX markup (Qwen-1.5B continuation). Removing formatting reduces 2v3 by ${\\sim}$1.8\\,pp but $\\Kempirical$ remains at 3 (CI lower $> \\theta$). LaTeX stripping fraction increases with depth (0.6\\% at depth 0, 4.6\\% at depth 5), deeper generations therefore produce proportionally more formatting tokens.}\n\\label{tab:latex_ablation}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccr}\n\\toprule\n\\textbf{Pair} & \\textbf{Original} & \\textbf{Stripped} & $\\Delta$ \\\\\n\\midrule\n0v1 & 0.9946 & 0.9948 & $+$0.0002 \\\\\n1v2 & 0.8580 & 0.8297 & $-$0.028 \\\\\n2v3 & 0.6427 $[0.628,\\,0.658]$ & 0.6248 $[0.610,\\,0.640]$ & $-$0.018 \\\\\n3v4 & 0.5437 & 0.5468 & $+$0.003 \\\\\n\\midrule\n$\\Kempirical$ & 3 & 3 & --- \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nContent-level statistical properties (surprisal distribution, vocabulary diversity) account for the large majority of the depth signal; LaTeX formatting contributes a modest but measurable increment (${\\sim}$1.8\\,pp at the boundary pair).\nThe depth-correlated increase in LaTeX stripping fraction (depth 0: $-$0.6\\%, depth 5: $-$4.6\\%) indicates that autoregressive generation progressively introduces formatting tokens, consistent with mode-seeking behavior in structured text.\n\n\\subsection{Statistical Power Analysis}\n\\label{sec:power_curve}\n\nTo characterize the minimum sample size required for reliable $\\Kempirical$ determination, we subsample C4 at $n \\in \\{500, 1000, 2000, 3000, 4000, 5000\\}$ and measure 1v2 AUC stability across 10 resamples per size (Qwen-1.5B-base continuation, 5-fold GroupKFold; Table~\\ref{tab:power_curve}, Figure~\\ref{fig:power_curve}).\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Subsampling power analysis for $\\Kempirical{=}2$ determination (C4, Qwen-1.5B-base, 10 resamples per $n$). Detection probability: fraction of resamples where 1v2 $\\auc > \\theta{=}0.60$.}\n\\label{tab:power_curve}\n\\begin{tabular}{rccc}\n\\toprule\n$n$ & \\textbf{Mean 1v2 $\\auc$} & \\textbf{Std} & \\textbf{Detection Prob.} \\\\\n\\midrule\n500 & 0.581 & 0.018 & 20\\% \\\\\n1{,}000 & 0.591 & 0.014 & 30\\% \\\\\n2{,}000 & 0.610 & 0.009 & 100\\% \\\\\n3{,}000 & 0.617 & 0.005 & 100\\% \\\\\n4{,}000 & 0.622 & 0.004 & 100\\% \\\\\n5{,}000 & 0.629 & 0.000 & 100\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[htbp]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_power_curve.png}\n\\caption{$\\Kempirical{=}2$ detection rate (left axis, blue) and mean 1v2 $\\auc$ (right axis, green) as a function of sample size $n$. Detection rate reaches 100\\% at $n{=}2{,}000$; the 80\\% power threshold (dotted purple) is crossed between $n{=}1{,}000$ and $n{=}2{,}000$. Error bars: $\\pm$1 std over 10 resamples. The dashed red line marks $\\theta{=}0.60$.}\n\\label{fig:power_curve}\n\\end{figure}\n\nDetection rate jumps from 20\\% ($n{=}500$) to 100\\% ($n{=}2{,}000$), with the 80\\% power threshold crossed near $n{=}1{,}500$.\nAt $n{=}5{,}000$ (the sample size used in all main experiments), variance is zero across resamples, our results are therefore well above the minimum required for reliable boundary estimation.\nThe sharp transition reflects the proximity of the 1v2 AUC to $\\theta$: small increases in $n$ reduce variance sufficiently to move all resamples above the threshold.\n\n\\subsection{Feature Group Ablation}\n\\label{sec:feature_ablation}\n\nTo assess the relative contribution of each feature group to depth discrimination, we train a plain LightGBM classifier (\\texttt{n\\_estimators}$=$200, \\texttt{max\\_depth}$=$6; distinct from the OBD-LightGBM used in Section~\\ref{sec:method}) on the 1\\,vs.\\,2 task using (a) each feature group alone (\\emph{single}) and (b) the full 15D set minus one group (\\emph{leave-one-out}).\nRepresentative models per domain: LLaMA-3.1-8B (C4), Qwen-1.5B continuation (arXiv), and the domain ablation configuration (Wikipedia).\n\n\\begin{figure}[htbp]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_feature_ablation.pdf}\n\\caption{Feature group ablation heatmap for 1\\,vs.\\,2 classification AUC. \\emph{Left}: single-group performance. \\emph{Right}: leave-one-out performance. Surprisal (base) features are the dominant signal on arXiv (single AUC $= 0.809$) but provide only weak marginal signal on C4 and Wikipedia.}\n\\label{fig:feature_ablation}\n\\end{figure}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Feature group ablation for 1\\,vs.\\,2 classification (AUC). \\textbf{Single}: using only features from one group. \\textbf{Leave-one-out}: removing one group from the full 15D feature set. $\\Delta$ denotes the AUC drop from the full model. Classifier: plain LightGBM (\\texttt{n\\_estimators}$=$200, \\texttt{max\\_depth}$=$6), distinct from the OBD-LightGBM pipeline; AUC values are not directly comparable to Table~\\ref{tab:kstar_ci}.}\n\\label{tab:feature_ablation}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{l ccc ccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{Single Group}} & \\multicolumn{3}{c}{\\textbf{Leave-One-Out ($\\Delta$)}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nFeature Group & C4 & arXiv & Wiki & C4 & arXiv & Wiki \\\\",
      "numLines": 300,
      "startLine": 300,
      "totalLines": 1090
    }
  },
  "sourceToolAssistantUUID": "3255c446-da0b-466d-a921-f8ecfa5606a3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 59_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "cf1d1f78-513a-4067-865f-216f5e985dc8",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 60_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Assistant

_source line 61 · 2026-05-21T06:35:12.737Z_

<details><summary>Logged reasoning block</summary>

```text
Let me continue reading the remaining portion of the appendix_extended.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cf1d1f78-513a-4067-865f-216f5e985dc8",
  "isSidechain": false,
  "requestId": "req_011CbFFS1jXTYtHryEXCgsWM",
  "type": "assistant",
  "uuid": "843c54d8-beda-48f0-ad94-27cc9bd8d791",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ExNPehdVqZi5EwuQBu97Av",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8830,
      "cache_read_input_tokens": 91151,
      "output_tokens": 154,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8830,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 154,
          "cache_read_input_tokens": 91151,
          "cache_creation_input_tokens": 8830,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8830
          },
          "type": "message"
        }
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

_source line 62 · 2026-05-21T06:35:14.305Z_

<details open><summary>🔧 Tool call — Read · `toolu_015cjja128WQgy4sUmVQwfF1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
  "offset": 600,
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "843c54d8-beda-48f0-ad94-27cc9bd8d791",
  "isSidechain": false,
  "requestId": "req_011CbFFS1jXTYtHryEXCgsWM",
  "type": "assistant",
  "uuid": "3520a540-25a9-469b-8895-4c2ffa51b41f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ExNPehdVqZi5EwuQBu97Av",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8830,
      "cache_read_input_tokens": 91151,
      "output_tokens": 154,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8830,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 154,
          "cache_read_input_tokens": 91151,
          "cache_creation_input_tokens": 8830,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8830
          },
          "type": "message"
        }
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

_source line 63 · 2026-05-21T06:35:14.327Z_

<details><summary>↩ Tool result · `toolu_015cjja128WQgy4sUmVQwfF1`</summary>

```text
600	\midrule
601	Surprisal (base) & 0.597 & 0.809 & 0.581 & 0.601 ($-$0.007) & 0.828 ($-$0.031) & 0.616 ($-$0.003) \\
602	Surprisal (deriv.) & 0.590 & 0.789 & 0.590 & 0.612 (+0.003) & 0.856 ($-$0.003) & 0.623 (+0.004) \\
603	Lexical diversity & 0.550 & 0.691 & 0.557 & 0.608 ($-$0.001) & 0.855 ($-$0.005) & 0.614 ($-$0.005) \\
604	Freq. distribution & 0.533 & 0.684 & 0.564 & 0.604 ($-$0.005) & 0.851 ($-$0.009) & 0.612 ($-$0.007) \\
605	\midrule
606	Full (15D) & 0.609 & 0.860 & 0.619 & \multicolumn{3}{c}{---} \\
607	\bottomrule
608	\end{tabular}}
609	\end{table}
610	
611	Surprisal (base) features dominate on arXiv (single-group AUC $= 0.809$; LOO drop $= 0.031$, the largest across all domain--group combinations), consistent with the persistent surprisal-distribution signal in structured academic text.
612	On C4 and Wikipedia, all LOO drops are small ($\leq 0.007$, within cross-fold standard deviation), no single feature group is therefore individually critical for the weaker low-$\Kempirical$ signal.
613	Removing surprisal derivatives increases AUC on C4 (+0.003) and Wikipedia (+0.004). This indicates partial redundancy with the base surprisal group in low-$\Kempirical$ domains.
614	
615	\subsection{Classifier Choice: McNemar Test}
616	\label{sec:mcnemar_baselines}
617	
618	To verify that depth discriminability is driven by the 15D feature representation rather than classifier choice, we compare OBD-LightGBM against three baseline classifiers (logistic regression, linear SVC, random forest) on the depth-1 vs.\ depth-2 binary classification task using McNemar's test with continuity correction on 5-fold GroupKFold out-of-fold predictions (Table~\ref{tab:mcnemar_obd_baselines}).
619	Of 36 comparisons, 31 are non-significant ($p \geq 0.05$), and all five significant results concentrate in two model $\times$ domain conditions.
620	For LLaMA-8B on C4, all three baselines significantly outperform OBD ($p \leq 0.001$), likely reflecting LightGBM overfitting on the relatively noisy 8B-generated features rather than a systematic classifier advantage.
621	For Qwen-1.5B on Wikipedia, OBD outperforms both linear classifiers ($p < 0.001$) but not random forest ($p = 0.655$).
622	
623	\begin{table*}[htbp]
624	\centering
625	\small
626	\caption{McNemar test $p$-values comparing OBD-LightGBM against baseline classifiers on the depth-1 vs.\ depth-2 binary classification task (5-fold GroupKFold, out-of-fold predictions). Classifier accuracy shown in parentheses. Significant results ($p < 0.05$) are \textbf{bold}; $^{*}p<0.05$, $^{**}p<0.01$, $^{***}p<0.001$.}
627	\label{tab:mcnemar_obd_baselines}
628	\resizebox{\textwidth}{!}{%
629	\begin{tabular}{llcccc}
630	\toprule
631	\textbf{Model} & \textbf{Domain} & \textbf{OBD Acc.} & \textbf{vs.\ LogReg} & \textbf{vs.\ LinearSVC} & \textbf{vs.\ RandomForest} \\
632	\midrule
633	Qwen-1.5B-base & C4    & .592 & .232 (.598)            & .605 (.595)              & .271 (.597) \\
634	Pythia-1.4B     & C4    & .631 & $\mathbf{.033^{*}}$ (.621) & .105 (.624)              & .451 (.628) \\
635	LLaMA-8B        & C4    & .573 & $\mathbf{6.2{\times}10^{-5\,***}}$ (.592) & $\mathbf{1.1{\times}10^{-4\,***}}$ (.591) & $\mathbf{.001^{**}}$ (.586) \\
636	\midrule
637	Qwen-1.5B      & Wiki  & .588 & $\mathbf{9.4{\times}10^{-4\,***}}$ (.570) & $\mathbf{2.3{\times}10^{-4\,***}}$ (.568) & .655 (.590) \\
638	Pythia          & Wiki  & .560 & .180 (.567)            & .540 (.564)              & .369 (.564) \\
639	OLMo            & Wiki  & .500 & .868 (.502)            & .705 (.503)              & .751 (.502) \\
640	LLaMA-8B        & Wiki  & .573 & .252 (.579)            & .270 (.579)              & .110 (.580) \\
641	\midrule
642	Qwen-1.5B      & arXiv & .781 & .156 (.774)            & .079 (.772)              & .364 (.777) \\
643	Pythia          & arXiv & .733 & .232 (.727)            & .384 (.728)              & .735 (.732) \\
644	OLMo            & arXiv & .493 & .520 (.487)            & .681 (.489)              & .759 (.496) \\
645	Qwen-7B         & arXiv & .757 & .160 (.749)            & .327 (.751)              & .733 (.758) \\
646	Mistral-7B      & arXiv & .742 & .524 (.738)            & .633 (.739)              & .225 (.748) \\
647	\bottomrule
648	\end{tabular}%
649	}
650	
651	\vspace{4pt}
652	\footnotesize
653	36 comparisons total. 5/36 reach $p < 0.05$; 4/36 reach $p < 0.01$.
654	The predominance of non-significant results confirms that depth discriminability is feature-driven, not classifier-driven.
655	\end{table*}
656	
657	\subsection{Domain Lexical Statistics}
658	\label{sec:domain_lexical_stats}
659	
660	Table~\ref{tab:domain-ttr-entropy} reports type-token ratio (TTR) and vocabulary entropy across three domains and six depth levels.
661	The TTR ordering at depth 0 (arXiv $>$ C4 $>$ Wikipedia) aligns with the $\Kempirical$ ordering, with large effect sizes (Cohen's $d = 1.52$ for arXiv vs.\ Wikipedia).
662	Vocabulary entropy shows a partial reversal at depth 0: C4 ($H = 6.225$) falls below Wikipedia ($H = 6.408$), while arXiv remains highest ($H = 6.853$).
663	This reversal likely reflects C4's greater content heterogeneity (higher variance: $\sigma = 0.706$ vs.\ $0.284$), which inflates TTR but depresses mean entropy.
664	As depth increases, all domains converge, with arXiv exhibiting the steepest decline, consistent with its higher $\Kempirical$ and slower convergence to the stationary distribution.
665	
666	\begin{table*}[htbp]
667	\centering
668	\small
669	\caption{Type-Token Ratio (TTR) and vocabulary entropy across three domains and generation depths.
670	At depth~0 (original human text), arXiv exhibits the highest lexical diversity (TTR\,=\,0.755, $H$\,=\,6.853),
671	followed by C4 and Wikipedia.
672	As depth increases, all domains converge, with arXiv showing the steepest decline.
673	Cohen's $d$ values are computed at depth~0 for pairwise domain comparisons.}
674	\label{tab:domain-ttr-entropy}
675	\begin{tabular}{ll rrr rrr}
676	\toprule
677	& & \multicolumn{3}{c}{\textbf{TTR}} & \multicolumn{3}{c}{\textbf{Vocab Entropy ($H$)}} \\
678	\cmidrule(lr){3-5} \cmidrule(lr){6-8}
679	\textbf{Depth} & $N$ & \textbf{Wiki} & \textbf{C4} & \textbf{arXiv} & \textbf{Wiki} & \textbf{C4} & \textbf{arXiv} \\
680	\midrule
681	0 & 5k/5k/2.2k & .665\tpm.061 & .720\tpm.105 & \textbf{.755}\tpm.055 & 6.408\tpm.284 & 6.225\tpm.706 & \textbf{6.853}\tpm.295 \\
682	1 &             & .655\tpm.121 & .707\tpm.149 & \textbf{.732}\tpm.098 & 5.932\tpm.843 & 5.737\tpm1.189 & \textbf{6.113}\tpm.655 \\
683	2 &             & .647\tpm.145 & .676\tpm.159 & \textbf{.677}\tpm.131 & 5.784\tpm.905 & 5.774\tpm1.139 & \textbf{5.998}\tpm.967 \\
684	3 &             & .645\tpm.159 & \textbf{.662}\tpm.164 & .635\tpm.134 & 5.664\tpm1.085 & 5.743\tpm1.161 & \textbf{5.964}\tpm.933 \\
685	4 &             & .636\tpm.164 & \textbf{.647}\tpm.169 & .621\tpm.140 & 5.660\tpm1.062 & 5.758\tpm1.167 & \textbf{5.898}\tpm.942 \\
686	5 &             & .632\tpm.172 & \textbf{.636}\tpm.175 & .618\tpm.150 & 5.593\tpm1.130 & 5.772\tpm1.141 & \textbf{5.816}\tpm.968 \\
687	\midrule
688	\multicolumn{8}{l}{\textit{Cohen's $d$ at depth 0 (positive $=$ second domain higher):}} \\
689	\multicolumn{2}{l}{C4 vs.\ Wiki}   & \multicolumn{3}{c}{$d = +0.65$} & \multicolumn{3}{c}{$d = -0.34$} \\
690	\multicolumn{2}{l}{arXiv vs.\ C4}  & \multicolumn{3}{c}{$d = +0.37$} & \multicolumn{3}{c}{$d = +1.03$} \\
691	\multicolumn{2}{l}{arXiv vs.\ Wiki} & \multicolumn{3}{c}{$d = +1.52$} & \multicolumn{3}{c}{$d = +1.55$} \\
692	\bottomrule
693	\end{tabular}
694	\end{table*}
695	
696	\subsection{Leave-One-Family-Out Threshold Validation}
697	\label{sec:theta_lofo}
698	
699	To validate $\theta{=}0.60$ without circular reasoning, we perform leave-one-family-out (LOFO) cross-validation: each fold removes one architecture family, derives $\hat{\theta}$ as the midpoint between $\min(\auc_{1v2})$ and $\max(\auc_{2v3})$ over the remaining families, then predicts $\Kempirical$ for the held-out models.
700	Table~\ref{tab:theta_lofo} reports results across all three domains.
701	
702	On C4, 8/10 held-out predictions agree with the original $\Kempirical$ assignment at $\theta{=}0.60$ (agreement: 80\%).
703	The two mismatches are Qwen-1.5B-RW (rewrite mode), whose 2v3 AUC of 0.5893 lies above the LOFO-derived $\hat{\theta}{=}0.5725$ but below the global $\theta{=}0.60$ (attributable to mode rather than threshold instability), and Gemma-2-2B, whose 1v2 AUC of 0.5981 exceeds $\hat{\theta}{=}0.5914$ ($\Kempirical_{\hat{\theta}}{=}2$) but falls below $\theta{=}0.60$ ($\Kempirical_{0.60}{=}1$).
704	The derived $\hat{\theta}$ values span $[0.5725, 0.5937]$; $\theta{=}0.60$ sits above this interval, making $\Kempirical$ assignments conservative lower bounds.
705	
706	ArXiv corroborates with 6/6 agreement (100\%), though the wide $\hat{\theta}$ range $[0.5735, 0.7296]$ reflects OLMo-1B's near-chance performance ($\auc_{1v2}{=}0.503$), which inflates the gap midpoint when OLMo is included in the training fold.
707	
708	Wikipedia yields only 1/6 agreement (17\%).
709	This failure is expected: most models produce near-chance 1v2 AUC on Wikipedia ($0.499$--$0.619$), so the gap between $\min(\auc_{1v2})$ and $\max(\auc_{2v3})$ is narrow or inverted, the gap-based threshold derivation is therefore invalid.
710	Wikipedia's $\Kempirical{=}1$ assignment is independently confirmed by the global $\theta{=}0.60$ criterion (Section~\ref{sec:cross_domain}); LOFO simply cannot validate this because the method requires a clear AUC discontinuity between boundary and non-boundary pairs.
711	
712	\begin{table*}[t]
713	\centering
714	\small
715	\caption{Leave-One-Family-Out (LOFO) cross-validation of $\theta$ across three domains. Each fold holds out one architecture family, derives $\hat{\theta}$ as the midpoint between $\min(\text{AUC}_{1\text{v}2})$ and $\max(\text{AUC}_{2\text{v}3})$ over the remaining families, and predicts $K^*$ for held-out models. C4 (primary): 8/10 agreement (80\%). arXiv: 6/6 (100\%). Wikipedia: 1/6 (17\%, see text).}
716	\label{tab:theta_lofo}
717	\begin{tabular}{l l l c c c c c c}
718	\toprule
719	Domain & Held-out & Model & $\text{AUC}_{1\text{v}2}$ & $\text{AUC}_{2\text{v}3}$ & $\hat{\theta}$ & $K^*_{\hat{\theta}}$ & $K^*_{0.60}$ & Match \\
720	\midrule
721	C4 & Pythia & Pythia-1.4B & 0.6539 & 0.5515 & 0.5914 & 2 & 2 & \cmark \\
722	 & OLMo & OLMo-1B & 0.6146 & 0.5497 & 0.5914 & 2 & 2 & \cmark \\
723	 & Qwen & Qwen-1.5B-RW & 0.6957 & 0.5893 & 0.5725 & 3 & 2 & \xmark \\
724	 &  & Qwen-7B & 0.6178 & 0.5460 & 0.5725 & 2 & 2 & \cmark \\
725	 &  & Qwen-1.5B-base & 0.6262 & 0.5496 & 0.5725 & 2 & 2 & \cmark \\
726	 &  & Qwen-1.5B-cont & 0.6114 & 0.5609 & 0.5725 & 2 & 2 & \cmark \\
727	 &  & Qwen-14B & 0.6210 & 0.5494 & 0.5725 & 2 & 2 & \cmark \\
728	 & LLaMA & LLaMA-3.1-8B & 0.6123 & 0.5274 & 0.5914 & 2 & 2 & \cmark \\
729	 & Mistral & Mistral-7B & 0.5935 & 0.5402 & 0.5937 & 1 & 1 & \cmark \\
730	 & Gemma & Gemma-2-2B & 0.5981 & 0.5342 & 0.5914 & 2 & 1 & \xmark \\
731	\cmidrule{2-9}
732	 & \multicolumn{7}{l}{$\hat{\theta}$ $\in$ [0.5725, 0.5937], agreement: 8/10 (80\%)} \\
733	\midrule
734	arXiv & Pythia & Pythia-1.4B & 0.8047 & 0.6545 & 0.5735 & 3 & 3 & \cmark \\
735	 & OLMo & OLMo-1B & 0.5034 & 0.5069 & 0.7296 & 1 & 1 & \cmark \\
736	 & Qwen & Qwen-1.5B & 0.8581 & 0.6436 & 0.5789 & 3 & 3 & \cmark \\
737	 &  & Qwen-7B & 0.8347 & 0.6255 & 0.5789 & 3 & 3 & \cmark \\
738	 & LLaMA & LLaMA-3.1-8B & 0.8447 & 0.6215 & 0.5789 & 3 & 3 & \cmark \\
739	 & Mistral & Mistral-7B & 0.8201 & 0.6275 & 0.5789 & 3 & 3 & \cmark \\
740	\cmidrule{2-9}
741	 & \multicolumn{7}{l}{$\hat{\theta}$ $\in$ [0.5735, 0.7296], agreement: 6/6 (100\%)} \\
742	\midrule
743	Wikipedia & Pythia & Pythia-1.4B & 0.5846 & 0.5445 & 0.5274 & 3 & 1 & \xmark \\
744	 & OLMo & OLMo-1B & 0.4986 & 0.5012 & 0.5557 & 1 & 1 & \cmark \\
745	 & Qwen & Qwen-1.5B & 0.6193 & 0.5498 & 0.5215 & 4 & 2 & \xmark \\
746	 &  & Qwen-7B & 0.6108 & 0.5562 & 0.5215 & 4 & 2 & \xmark \\
747	 & LLaMA & LLaMA-3.1-8B & 0.5954 & 0.5392 & 0.5274 & 3 & 1 & \xmark \\
748	 & Mistral & Mistral-7B & 0.5552 & 0.5236 & 0.5274 & 2 & 1 & \xmark \\
749	\cmidrule{2-9}
750	 & \multicolumn{7}{l}{$\hat{\theta}$ $\in$ [0.5215, 0.5557], agreement: 1/6 (17\%)} \\
751	\bottomrule
752	\end{tabular}
753	\end{table*}
754	
755	\paragraph{Family-split held-out validation.}
756	As a complementary check, we split the six families by scorer affinity: the five non-Qwen families (Gemma-2-2B, OLMo-1B, Pythia-1.4B, LLaMA-3.1-8B, Mistral-7B) derive $\hat{\theta}$, and the three Qwen configurations (Qwen-1.5B-RW, Qwen-1.5B-cont, Qwen-7B) serve as held-out validation.
757	Table~\ref{tab:nonqwen_split} reports the split.
758	The non-Qwen consensus falls within $(0.54, 0.58]$; all three Qwen configurations exceed this range with positive margins, yielding $\Kempirical{=}2$ at $\hat{\theta}{=}0.58$.
759	This confirms that $\theta$ is not overfit to the scorer family: the boundary holds on architecturally distinct held-out generators.
760	
761	\begin{table}[t]
762	\centering
763	\small
764	\caption{Family-split held-out validation. \textbf{Derivation}: $\hat{\theta}$ derived from five non-Qwen families (consensus $(0.54, 0.58]$). \textbf{Validation}: three Qwen configurations evaluated at $\hat{\theta}{=}0.58$; all yield $\Kempirical{=}2$.}
765	\label{tab:nonqwen_split}
766	\begin{tabular}{l l c c c}
767	\toprule
768	\textbf{Panel} & \textbf{Family} & $\text{AUC}_{1\text{v}2}$ CI$_\text{low}$ & $K^*_{\hat{\theta}=0.58}$ & Margin \\
769	\midrule
770	\multicolumn{5}{l}{\emph{Derivation (non-Qwen)}} \\
771	 & Gemma-2-2B   & 0.5882 & 2 & --- \\
772	 & OLMo-1B      & 0.6045 & 2 & --- \\
773	 & Pythia-1.4B  & 0.6454 & 2 & --- \\
774	 & LLaMA-3.1-8B & 0.6028 & 2 & --- \\
775	 & Mistral-7B   & 0.5835 & 1 & --- \\
776	\cmidrule{2-5}
777	 & \multicolumn{4}{l}{Consensus $\hat{\theta} \in (0.54, 0.58]$} \\
778	\midrule
779	\multicolumn{5}{l}{\emph{Validation (Qwen)}} \\
780	 & Qwen-1.5B-RW   & 0.6859 & 2 & $+$0.106 \\
781	 & Qwen-1.5B-cont & 0.6015 & 2 & $+$0.022 \\
782	 & Qwen-7B        & 0.6080 & 2 & $+$0.028 \\
783	\cmidrule{2-5}
784	 & \multicolumn{4}{l}{3/3 agreement (100\%)} \\
785	\bottomrule
786	\end{tabular}
787	\end{table}
788	
789	\subsection{Code Domain Results}
790	\label{sec:code_domain}
791	
792	\begin{table}[htbp]
793	\centering
794	\small
795	\caption{Code domain (Python, CodeSearchNet~\cite{husain2019codesearchnet}) pairwise AUC for Qwen2.5-1.5B. $\Kempirical{=}2$: 1v2 exceeds $\theta{=}0.60$; 2v3 drops to chance. JSD ratio (1v2/2v3) $= 11.7\times$, comparable to C4's cliff structure.}
796	\label{tab:code_domain_qwen}
797	\begin{tabular}{l c c c}
798	\toprule
799	Pair & AUC & 95\% CI & JSD \\
800	\midrule
801	0 vs 1 & 0.9388 & [0.929, 0.949] & 0.0814 \\
802	1 vs 2 & 0.7382 & [0.709, 0.767] & 0.0443 \\
803	2 vs 3 & 0.5300 & [0.514, 0.546] & 0.0038 \\
804	3 vs 4 & 0.5022 & [0.486, 0.518] & 0.0033 \\
805	4 vs 5 & 0.5219 & [0.510, 0.534] & 0.0030 \\
806	\midrule
807	\multicolumn{4}{l}{$\Kempirical = 2$ ($\theta = 0.60$)} \\
808	\bottomrule
809	\end{tabular}
810	\end{table}
811	
812	\begin{table}[htbp]
813	\centering
814	\small
815	\caption{Code domain (Python, CodeSearchNet) cross-model pairwise AUC with 5-fold cross-validated 95\% CIs across five models (four architecture families). Qwen2.5-1.5B/7B, LLaMA-3.1-8B, and Mistral-7B-v0.3 yield $\Kempirical{=}2$ (4/5); Pythia-1.4B yields $\Kempirical{=}1$ (capacity-limited). All models scored by Qwen2.5-1.5B (cross-family for non-Qwen).}
816	\label{tab:code_crossmodel_kstar}
817	\resizebox{\columnwidth}{!}{%
818	\begin{tabular}{l cc cc cc cc cc}
819	\toprule
820	 & \multicolumn{2}{c}{Qwen-1.5B} & \multicolumn{2}{c}{Qwen-7B} & \multicolumn{2}{c}{Pythia-1.4B} & \multicolumn{2}{c}{LLaMA-8B} & \multicolumn{2}{c}{Mistral-7B} \\
821	\cmidrule(lr){2-3}\cmidrule(lr){4-5}\cmidrule(lr){6-7}\cmidrule(lr){8-9}\cmidrule(lr){10-11}
822	 & AUC & 95\% CI & AUC & 95\% CI & AUC & 95\% CI & AUC & 95\% CI & AUC & 95\% CI \\
823	\midrule
824	0v1 & .9388 & [.929,\,.949] & .9051 & [.901,\,.909] & \textbf{.9592} & [.956,\,.963] & .9161 & [.912,\,.920] & .9191 & [.917,\,.921] \\
825	1v2 & \textbf{.7382} & [.709,\,.767]\rlap{$^*$} & .7276 & [.722,\,.733]\rlap{$^*$} & .5983 & [.593,\,.603] & \textbf{.7394} & [.729,\,.750]\rlap{$^*$} & .6152 & [.603,\,.627]\rlap{$^*$} \\
826	2v3 & .5300 & [.514,\,.546] & .5368 & [.522,\,.551] & .5215 & [.509,\,.534] & .5112 & [.502,\,.521] & .5293 & [.520,\,.538] \\
827	3v4 & .5022 & [.486,\,.518] & .5090 & [.504,\,.515] & .5152 & [.503,\,.527] & .5200 & [.506,\,.534] & .5286 & [.518,\,.539] \\
828	4v5 & .5219 & [.510,\,.534] & .5139 & [.501,\,.527] & .5046 & [.491,\,.518] & .4996 & [.493,\,.507] & .5099 & [.504,\,.516] \\
829	\midrule
830	$K^*$ & \multicolumn{2}{c}{\textbf{2}} & \multicolumn{2}{c}{\textbf{2}} & \multicolumn{2}{c}{1} & \multicolumn{2}{c}{\textbf{2}} & \multicolumn{2}{c}{\textbf{2}} \\
831	\bottomrule
832	\multicolumn{11}{@{}p{\linewidth}@{}}{\footnotesize $^*$Permutation $p < 0.001$. $K^*$: max $k$ where $k$v$(k{+}1)$ CI lower bound $> \theta = 0.60$ (Eq.~\ref{eq:kstar}).}
833	\end{tabular}}
834	\end{table}
835	
836	\paragraph{Cross-scorer validation (Code domain).}
837	To rule out scorer confound for Code $\Kempirical{=}2$, we re-evaluate Qwen2.5-1.5B code generations using Pythia-1.4B as the reference scorer (Table~\ref{tab:code_crossscorer}).
838	Cross-family scoring yields $\Kempirical{=}2$ (1v2 $\auc = 0.7197$, five-fold minimum $= 0.6985$, all folds above $\theta$), a decrease of only 1.9\,pp from Qwen self-scoring ($0.7382$).
839	This contrasts with Wikipedia, where same-family scoring inflates $\Kempirical$ from 1 to 2 (Appendix~\ref{sec:wiki_domain}): Code depth signal is robust to scorer choice, while Wikipedia's marginal signal is scorer-sensitive.
840	The scorer confound is therefore domain-specific rather than systematic.
841	
842	\begin{table}[htbp]
843	\centering
844	\small
845	\caption{Code domain cross-scorer validation: Pythia-1.4B scorer on Qwen2.5-1.5B code generations. $\Kempirical{=}2$ is preserved; five-fold minimum 1v2 $\auc = 0.6985$, well above $\theta{=}0.60$.}
846	\label{tab:code_crossscorer}
847	\begin{tabular}{lcc}
848	\toprule
849	Scorer & 1v2 $\auc$ & 5-fold min \\
850	\midrule
851	Qwen2.5-1.5B (self) & 0.7382 & 0.7093 \\
852	Pythia-1.4B (cross) & 0.7197 & 0.6985 \\
853	\midrule
854	$\Delta$ & \multicolumn{2}{c}{$-1.9$\,pp} \\
855	$\Kempirical$ & \multicolumn{2}{c}{2 (both)} \\
856	\bottomrule
857	\end{tabular}
858	\end{table}
859	
860	\subsection{Borderline Feature Analysis}
861	\label{sec:borderline_analysis}
862	
863	To understand why Mistral-7B yields $\Kempirical{=}1$ while other C4 models yield $\Kempirical{=}2$, we compute per-feature Cohen's $d$ (depth-1 vs.\ depth-2) and LightGBM feature importances across six C4 configurations spanning the full 1v2 AUC range (0.594--0.884).
864	
865	Mistral-7B exhibits the lowest depth-0 mean surprisal (2.32 vs.\ 2.90--3.02 for other models), the scorer model therefore already finds Mistral's output highly predictable.
866	This compressed baseline limits the dynamic range available for detecting inter-generational degradation: all 15 Cohen's $d$ values are weak ($\bar{|d|} = 0.112$; Table~\ref{tab:cohens_d_full}), and no single feature exceeds 13\% of total classifier importance.
867	The borderline models (LLaMA-8B, Pythia at $T{=}1.2$) show a similar pattern at slightly higher effect sizes.
868	
869	Greedy decoding is qualitatively distinct: Pythia-greedy achieves 0.884 AUC via lexical collapse (hapax ratio $d = -1.056$, capturing 47\% of importance), a signal absent under sampling-based generation where all non-greedy models rely on surprisal variability features.
870	
871	\begin{table*}[htbp]
872	\centering
873	\small
874	\caption{Feature-level summary of C4 1v2 classification across model categories. Imp.\ = normalized LightGBM gain importance (\%). $\bar{|d|}$ = mean absolute Cohen's $d$ over all 15 features. $\Delta\text{surp}_{1\to2}$: change in mean surprisal from depth 1 to depth 2.}
875	\label{tab:borderline_features}
876	\begin{tabular}{@{}llc lcc@{}}
877	\toprule
878	Category & Model & AUC & Top-3 Features (Imp.\%) & $\bar{|d|}$ & $\Delta\text{surp}_{1\to2}$ \\
879	\midrule
880	Strong & Pythia-greedy & 0.884 & hapax\_ratio (47), surp\_mean (11), low\_freq\_ratio (8) & 0.365 & $-$0.160 \\
881	Strong & Pythia-nuc09 & 0.677 & surp\_std (20), freq\_entropy (11), surp\_d1\_std (8) & 0.170 & $-$0.196 \\
882	Strong & Qwen-1.5B-base & 0.626 & surp\_std (13), freq\_entropy (10), surp\_mean (9) & 0.125 & $-$0.159 \\
883	\midrule
884	Borderline & Pythia-$T{=}1.2$ & 0.617 & surp\_std (15), freq\_entropy (10), surp\_kurt (8) & 0.112 & $-$0.059 \\
885	Borderline & LLaMA-3.1-8B & 0.612 & surp\_std (12), surp\_d1\_std (10), freq\_entropy (9) & 0.137 & $-$0.215 \\
886	\midrule
887	Below $\theta$ & Mistral-7B & 0.594 & surp\_std (13), freq\_entropy (9), surp\_d1\_skew (9) & 0.112 & $-$0.086 \\
888	\bottomrule
889	\end{tabular}
890	\end{table*}
891	
892	\begin{table*}[htbp]
893	\centering
894	\scriptsize
895	\caption{Cohen's $d$ (depth-1 vs.\ depth-2) for all 15 features across six C4 models. \textbf{Bold}: largest $|d|$ in each row. Greedy decoding produces qualitatively different effect sizes via lexical collapse (hapax\_ratio, low\_freq\_ratio); under sampling, surprisal variability features (surp\_std, surp\_d1\_std, surp\_d2\_std) carry the dominant signal.}
896	\label{tab:cohens_d_full}
897	\begin{tabular}{@{}lrrrrrr@{}}
898	\toprule
899	Feature & \rotatebox{60}{Pythia-greedy} & \rotatebox{60}{Pythia-nuc09} & \rotatebox{60}{Qwen-1.5B-base} & \rotatebox{60}{Pythia-$T{=}1.2$} & \rotatebox{60}{LLaMA-3.1-8B} & \rotatebox{60}{Mistral-7B} \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3520a540-25a9-469b-8895-4c2ffa51b41f",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "05987c5d-e85f-4aa9-8d15-53e093342c14",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
      "content": "\\midrule\nSurprisal (base) & 0.597 & 0.809 & 0.581 & 0.601 ($-$0.007) & 0.828 ($-$0.031) & 0.616 ($-$0.003) \\\\\nSurprisal (deriv.) & 0.590 & 0.789 & 0.590 & 0.612 (+0.003) & 0.856 ($-$0.003) & 0.623 (+0.004) \\\\\nLexical diversity & 0.550 & 0.691 & 0.557 & 0.608 ($-$0.001) & 0.855 ($-$0.005) & 0.614 ($-$0.005) \\\\\nFreq. distribution & 0.533 & 0.684 & 0.564 & 0.604 ($-$0.005) & 0.851 ($-$0.009) & 0.612 ($-$0.007) \\\\\n\\midrule\nFull (15D) & 0.609 & 0.860 & 0.619 & \\multicolumn{3}{c}{---} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nSurprisal (base) features dominate on arXiv (single-group AUC $= 0.809$; LOO drop $= 0.031$, the largest across all domain--group combinations), consistent with the persistent surprisal-distribution signal in structured academic text.\nOn C4 and Wikipedia, all LOO drops are small ($\\leq 0.007$, within cross-fold standard deviation), no single feature group is therefore individually critical for the weaker low-$\\Kempirical$ signal.\nRemoving surprisal derivatives increases AUC on C4 (+0.003) and Wikipedia (+0.004). This indicates partial redundancy with the base surprisal group in low-$\\Kempirical$ domains.\n\n\\subsection{Classifier Choice: McNemar Test}\n\\label{sec:mcnemar_baselines}\n\nTo verify that depth discriminability is driven by the 15D feature representation rather than classifier choice, we compare OBD-LightGBM against three baseline classifiers (logistic regression, linear SVC, random forest) on the depth-1 vs.\\ depth-2 binary classification task using McNemar's test with continuity correction on 5-fold GroupKFold out-of-fold predictions (Table~\\ref{tab:mcnemar_obd_baselines}).\nOf 36 comparisons, 31 are non-significant ($p \\geq 0.05$), and all five significant results concentrate in two model $\\times$ domain conditions.\nFor LLaMA-8B on C4, all three baselines significantly outperform OBD ($p \\leq 0.001$), likely reflecting LightGBM overfitting on the relatively noisy 8B-generated features rather than a systematic classifier advantage.\nFor Qwen-1.5B on Wikipedia, OBD outperforms both linear classifiers ($p < 0.001$) but not random forest ($p = 0.655$).\n\n\\begin{table*}[htbp]\n\\centering\n\\small\n\\caption{McNemar test $p$-values comparing OBD-LightGBM against baseline classifiers on the depth-1 vs.\\ depth-2 binary classification task (5-fold GroupKFold, out-of-fold predictions). Classifier accuracy shown in parentheses. Significant results ($p < 0.05$) are \\textbf{bold}; $^{*}p<0.05$, $^{**}p<0.01$, $^{***}p<0.001$.}\n\\label{tab:mcnemar_obd_baselines}\n\\resizebox{\\textwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Domain} & \\textbf{OBD Acc.} & \\textbf{vs.\\ LogReg} & \\textbf{vs.\\ LinearSVC} & \\textbf{vs.\\ RandomForest} \\\\\n\\midrule\nQwen-1.5B-base & C4    & .592 & .232 (.598)            & .605 (.595)              & .271 (.597) \\\\\nPythia-1.4B     & C4    & .631 & $\\mathbf{.033^{*}}$ (.621) & .105 (.624)              & .451 (.628) \\\\\nLLaMA-8B        & C4    & .573 & $\\mathbf{6.2{\\times}10^{-5\\,***}}$ (.592) & $\\mathbf{1.1{\\times}10^{-4\\,***}}$ (.591) & $\\mathbf{.001^{**}}$ (.586) \\\\\n\\midrule\nQwen-1.5B      & Wiki  & .588 & $\\mathbf{9.4{\\times}10^{-4\\,***}}$ (.570) & $\\mathbf{2.3{\\times}10^{-4\\,***}}$ (.568) & .655 (.590) \\\\\nPythia          & Wiki  & .560 & .180 (.567)            & .540 (.564)              & .369 (.564) \\\\\nOLMo            & Wiki  & .500 & .868 (.502)            & .705 (.503)              & .751 (.502) \\\\\nLLaMA-8B        & Wiki  & .573 & .252 (.579)            & .270 (.579)              & .110 (.580) \\\\\n\\midrule\nQwen-1.5B      & arXiv & .781 & .156 (.774)            & .079 (.772)              & .364 (.777) \\\\\nPythia          & arXiv & .733 & .232 (.727)            & .384 (.728)              & .735 (.732) \\\\\nOLMo            & arXiv & .493 & .520 (.487)            & .681 (.489)              & .759 (.496) \\\\\nQwen-7B         & arXiv & .757 & .160 (.749)            & .327 (.751)              & .733 (.758) \\\\\nMistral-7B      & arXiv & .742 & .524 (.738)            & .633 (.739)              & .225 (.748) \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\n\\vspace{4pt}\n\\footnotesize\n36 comparisons total. 5/36 reach $p < 0.05$; 4/36 reach $p < 0.01$.\nThe predominance of non-significant results confirms that depth discriminability is feature-driven, not classifier-driven.\n\\end{table*}\n\n\\subsection{Domain Lexical Statistics}\n\\label{sec:domain_lexical_stats}\n\nTable~\\ref{tab:domain-ttr-entropy} reports type-token ratio (TTR) and vocabulary entropy across three domains and six depth levels.\nThe TTR ordering at depth 0 (arXiv $>$ C4 $>$ Wikipedia) aligns with the $\\Kempirical$ ordering, with large effect sizes (Cohen's $d = 1.52$ for arXiv vs.\\ Wikipedia).\nVocabulary entropy shows a partial reversal at depth 0: C4 ($H = 6.225$) falls below Wikipedia ($H = 6.408$), while arXiv remains highest ($H = 6.853$).\nThis reversal likely reflects C4's greater content heterogeneity (higher variance: $\\sigma = 0.706$ vs.\\ $0.284$), which inflates TTR but depresses mean entropy.\nAs depth increases, all domains converge, with arXiv exhibiting the steepest decline, consistent with its higher $\\Kempirical$ and slower convergence to the stationary distribution.\n\n\\begin{table*}[htbp]\n\\centering\n\\small\n\\caption{Type-Token Ratio (TTR) and vocabulary entropy across three domains and generation depths.\nAt depth~0 (original human text), arXiv exhibits the highest lexical diversity (TTR\\,=\\,0.755, $H$\\,=\\,6.853),\nfollowed by C4 and Wikipedia.\nAs depth increases, all domains converge, with arXiv showing the steepest decline.\nCohen's $d$ values are computed at depth~0 for pairwise domain comparisons.}\n\\label{tab:domain-ttr-entropy}\n\\begin{tabular}{ll rrr rrr}\n\\toprule\n& & \\multicolumn{3}{c}{\\textbf{TTR}} & \\multicolumn{3}{c}{\\textbf{Vocab Entropy ($H$)}} \\\\\n\\cmidrule(lr){3-5} \\cmidrule(lr){6-8}\n\\textbf{Depth} & $N$ & \\textbf{Wiki} & \\textbf{C4} & \\textbf{arXiv} & \\textbf{Wiki} & \\textbf{C4} & \\textbf{arXiv} \\\\\n\\midrule\n0 & 5k/5k/2.2k & .665\\tpm.061 & .720\\tpm.105 & \\textbf{.755}\\tpm.055 & 6.408\\tpm.284 & 6.225\\tpm.706 & \\textbf{6.853}\\tpm.295 \\\\\n1 &             & .655\\tpm.121 & .707\\tpm.149 & \\textbf{.732}\\tpm.098 & 5.932\\tpm.843 & 5.737\\tpm1.189 & \\textbf{6.113}\\tpm.655 \\\\\n2 &             & .647\\tpm.145 & .676\\tpm.159 & \\textbf{.677}\\tpm.131 & 5.784\\tpm.905 & 5.774\\tpm1.139 & \\textbf{5.998}\\tpm.967 \\\\\n3 &             & .645\\tpm.159 & \\textbf{.662}\\tpm.164 & .635\\tpm.134 & 5.664\\tpm1.085 & 5.743\\tpm1.161 & \\textbf{5.964}\\tpm.933 \\\\\n4 &             & .636\\tpm.164 & \\textbf{.647}\\tpm.169 & .621\\tpm.140 & 5.660\\tpm1.062 & 5.758\\tpm1.167 & \\textbf{5.898}\\tpm.942 \\\\\n5 &             & .632\\tpm.172 & \\textbf{.636}\\tpm.175 & .618\\tpm.150 & 5.593\\tpm1.130 & 5.772\\tpm1.141 & \\textbf{5.816}\\tpm.968 \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cohen's $d$ at depth 0 (positive $=$ second domain higher):}} \\\\\n\\multicolumn{2}{l}{C4 vs.\\ Wiki}   & \\multicolumn{3}{c}{$d = +0.65$} & \\multicolumn{3}{c}{$d = -0.34$} \\\\\n\\multicolumn{2}{l}{arXiv vs.\\ C4}  & \\multicolumn{3}{c}{$d = +0.37$} & \\multicolumn{3}{c}{$d = +1.03$} \\\\\n\\multicolumn{2}{l}{arXiv vs.\\ Wiki} & \\multicolumn{3}{c}{$d = +1.52$} & \\multicolumn{3}{c}{$d = +1.55$} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Leave-One-Family-Out Threshold Validation}\n\\label{sec:theta_lofo}\n\nTo validate $\\theta{=}0.60$ without circular reasoning, we perform leave-one-family-out (LOFO) cross-validation: each fold removes one architecture family, derives $\\hat{\\theta}$ as the midpoint between $\\min(\\auc_{1v2})$ and $\\max(\\auc_{2v3})$ over the remaining families, then predicts $\\Kempirical$ for the held-out models.\nTable~\\ref{tab:theta_lofo} reports results across all three domains.\n\nOn C4, 8/10 held-out predictions agree with the original $\\Kempirical$ assignment at $\\theta{=}0.60$ (agreement: 80\\%).\nThe two mismatches are Qwen-1.5B-RW (rewrite mode), whose 2v3 AUC of 0.5893 lies above the LOFO-derived $\\hat{\\theta}{=}0.5725$ but below the global $\\theta{=}0.60$ (attributable to mode rather than threshold instability), and Gemma-2-2B, whose 1v2 AUC of 0.5981 exceeds $\\hat{\\theta}{=}0.5914$ ($\\Kempirical_{\\hat{\\theta}}{=}2$) but falls below $\\theta{=}0.60$ ($\\Kempirical_{0.60}{=}1$).\nThe derived $\\hat{\\theta}$ values span $[0.5725, 0.5937]$; $\\theta{=}0.60$ sits above this interval, making $\\Kempirical$ assignments conservative lower bounds.\n\nArXiv corroborates with 6/6 agreement (100\\%), though the wide $\\hat{\\theta}$ range $[0.5735, 0.7296]$ reflects OLMo-1B's near-chance performance ($\\auc_{1v2}{=}0.503$), which inflates the gap midpoint when OLMo is included in the training fold.\n\nWikipedia yields only 1/6 agreement (17\\%).\nThis failure is expected: most models produce near-chance 1v2 AUC on Wikipedia ($0.499$--$0.619$), so the gap between $\\min(\\auc_{1v2})$ and $\\max(\\auc_{2v3})$ is narrow or inverted, the gap-based threshold derivation is therefore invalid.\nWikipedia's $\\Kempirical{=}1$ assignment is independently confirmed by the global $\\theta{=}0.60$ criterion (Section~\\ref{sec:cross_domain}); LOFO simply cannot validate this because the method requires a clear AUC discontinuity between boundary and non-boundary pairs.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Leave-One-Family-Out (LOFO) cross-validation of $\\theta$ across three domains. Each fold holds out one architecture family, derives $\\hat{\\theta}$ as the midpoint between $\\min(\\text{AUC}_{1\\text{v}2})$ and $\\max(\\text{AUC}_{2\\text{v}3})$ over the remaining families, and predicts $K^*$ for held-out models. C4 (primary): 8/10 agreement (80\\%). arXiv: 6/6 (100\\%). Wikipedia: 1/6 (17\\%, see text).}\n\\label{tab:theta_lofo}\n\\begin{tabular}{l l l c c c c c c}\n\\toprule\nDomain & Held-out & Model & $\\text{AUC}_{1\\text{v}2}$ & $\\text{AUC}_{2\\text{v}3}$ & $\\hat{\\theta}$ & $K^*_{\\hat{\\theta}}$ & $K^*_{0.60}$ & Match \\\\\n\\midrule\nC4 & Pythia & Pythia-1.4B & 0.6539 & 0.5515 & 0.5914 & 2 & 2 & \\cmark \\\\\n & OLMo & OLMo-1B & 0.6146 & 0.5497 & 0.5914 & 2 & 2 & \\cmark \\\\\n & Qwen & Qwen-1.5B-RW & 0.6957 & 0.5893 & 0.5725 & 3 & 2 & \\xmark \\\\\n &  & Qwen-7B & 0.6178 & 0.5460 & 0.5725 & 2 & 2 & \\cmark \\\\\n &  & Qwen-1.5B-base & 0.6262 & 0.5496 & 0.5725 & 2 & 2 & \\cmark \\\\\n &  & Qwen-1.5B-cont & 0.6114 & 0.5609 & 0.5725 & 2 & 2 & \\cmark \\\\\n &  & Qwen-14B & 0.6210 & 0.5494 & 0.5725 & 2 & 2 & \\cmark \\\\\n & LLaMA & LLaMA-3.1-8B & 0.6123 & 0.5274 & 0.5914 & 2 & 2 & \\cmark \\\\\n & Mistral & Mistral-7B & 0.5935 & 0.5402 & 0.5937 & 1 & 1 & \\cmark \\\\\n & Gemma & Gemma-2-2B & 0.5981 & 0.5342 & 0.5914 & 2 & 1 & \\xmark \\\\\n\\cmidrule{2-9}\n & \\multicolumn{7}{l}{$\\hat{\\theta}$ $\\in$ [0.5725, 0.5937], agreement: 8/10 (80\\%)} \\\\\n\\midrule\narXiv & Pythia & Pythia-1.4B & 0.8047 & 0.6545 & 0.5735 & 3 & 3 & \\cmark \\\\\n & OLMo & OLMo-1B & 0.5034 & 0.5069 & 0.7296 & 1 & 1 & \\cmark \\\\\n & Qwen & Qwen-1.5B & 0.8581 & 0.6436 & 0.5789 & 3 & 3 & \\cmark \\\\\n &  & Qwen-7B & 0.8347 & 0.6255 & 0.5789 & 3 & 3 & \\cmark \\\\\n & LLaMA & LLaMA-3.1-8B & 0.8447 & 0.6215 & 0.5789 & 3 & 3 & \\cmark \\\\\n & Mistral & Mistral-7B & 0.8201 & 0.6275 & 0.5789 & 3 & 3 & \\cmark \\\\\n\\cmidrule{2-9}\n & \\multicolumn{7}{l}{$\\hat{\\theta}$ $\\in$ [0.5735, 0.7296], agreement: 6/6 (100\\%)} \\\\\n\\midrule\nWikipedia & Pythia & Pythia-1.4B & 0.5846 & 0.5445 & 0.5274 & 3 & 1 & \\xmark \\\\\n & OLMo & OLMo-1B & 0.4986 & 0.5012 & 0.5557 & 1 & 1 & \\cmark \\\\\n & Qwen & Qwen-1.5B & 0.6193 & 0.5498 & 0.5215 & 4 & 2 & \\xmark \\\\\n &  & Qwen-7B & 0.6108 & 0.5562 & 0.5215 & 4 & 2 & \\xmark \\\\\n & LLaMA & LLaMA-3.1-8B & 0.5954 & 0.5392 & 0.5274 & 3 & 1 & \\xmark \\\\\n & Mistral & Mistral-7B & 0.5552 & 0.5236 & 0.5274 & 2 & 1 & \\xmark \\\\\n\\cmidrule{2-9}\n & \\multicolumn{7}{l}{$\\hat{\\theta}$ $\\in$ [0.5215, 0.5557], agreement: 1/6 (17\\%)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\paragraph{Family-split held-out validation.}\nAs a complementary check, we split the six families by scorer affinity: the five non-Qwen families (Gemma-2-2B, OLMo-1B, Pythia-1.4B, LLaMA-3.1-8B, Mistral-7B) derive $\\hat{\\theta}$, and the three Qwen configurations (Qwen-1.5B-RW, Qwen-1.5B-cont, Qwen-7B) serve as held-out validation.\nTable~\\ref{tab:nonqwen_split} reports the split.\nThe non-Qwen consensus falls within $(0.54, 0.58]$; all three Qwen configurations exceed this range with positive margins, yielding $\\Kempirical{=}2$ at $\\hat{\\theta}{=}0.58$.\nThis confirms that $\\theta$ is not overfit to the scorer family: the boundary holds on architecturally distinct held-out generators.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Family-split held-out validation. \\textbf{Derivation}: $\\hat{\\theta}$ derived from five non-Qwen families (consensus $(0.54, 0.58]$). \\textbf{Validation}: three Qwen configurations evaluated at $\\hat{\\theta}{=}0.58$; all yield $\\Kempirical{=}2$.}\n\\label{tab:nonqwen_split}\n\\begin{tabular}{l l c c c}\n\\toprule\n\\textbf{Panel} & \\textbf{Family} & $\\text{AUC}_{1\\text{v}2}$ CI$_\\text{low}$ & $K^*_{\\hat{\\theta}=0.58}$ & Margin \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{Derivation (non-Qwen)}} \\\\\n & Gemma-2-2B   & 0.5882 & 2 & --- \\\\\n & OLMo-1B      & 0.6045 & 2 & --- \\\\\n & Pythia-1.4B  & 0.6454 & 2 & --- \\\\\n & LLaMA-3.1-8B & 0.6028 & 2 & --- \\\\\n & Mistral-7B   & 0.5835 & 1 & --- \\\\\n\\cmidrule{2-5}\n & \\multicolumn{4}{l}{Consensus $\\hat{\\theta} \\in (0.54, 0.58]$} \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{Validation (Qwen)}} \\\\\n & Qwen-1.5B-RW   & 0.6859 & 2 & $+$0.106 \\\\\n & Qwen-1.5B-cont & 0.6015 & 2 & $+$0.022 \\\\\n & Qwen-7B        & 0.6080 & 2 & $+$0.028 \\\\\n\\cmidrule{2-5}\n & \\multicolumn{4}{l}{3/3 agreement (100\\%)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Code Domain Results}\n\\label{sec:code_domain}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Code domain (Python, CodeSearchNet~\\cite{husain2019codesearchnet}) pairwise AUC for Qwen2.5-1.5B. $\\Kempirical{=}2$: 1v2 exceeds $\\theta{=}0.60$; 2v3 drops to chance. JSD ratio (1v2/2v3) $= 11.7\\times$, comparable to C4's cliff structure.}\n\\label{tab:code_domain_qwen}\n\\begin{tabular}{l c c c}\n\\toprule\nPair & AUC & 95\\% CI & JSD \\\\\n\\midrule\n0 vs 1 & 0.9388 & [0.929, 0.949] & 0.0814 \\\\\n1 vs 2 & 0.7382 & [0.709, 0.767] & 0.0443 \\\\\n2 vs 3 & 0.5300 & [0.514, 0.546] & 0.0038 \\\\\n3 vs 4 & 0.5022 & [0.486, 0.518] & 0.0033 \\\\\n4 vs 5 & 0.5219 & [0.510, 0.534] & 0.0030 \\\\\n\\midrule\n\\multicolumn{4}{l}{$\\Kempirical = 2$ ($\\theta = 0.60$)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Code domain (Python, CodeSearchNet) cross-model pairwise AUC with 5-fold cross-validated 95\\% CIs across five models (four architecture families). Qwen2.5-1.5B/7B, LLaMA-3.1-8B, and Mistral-7B-v0.3 yield $\\Kempirical{=}2$ (4/5); Pythia-1.4B yields $\\Kempirical{=}1$ (capacity-limited). All models scored by Qwen2.5-1.5B (cross-family for non-Qwen).}\n\\label{tab:code_crossmodel_kstar}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{l cc cc cc cc cc}\n\\toprule\n & \\multicolumn{2}{c}{Qwen-1.5B} & \\multicolumn{2}{c}{Qwen-7B} & \\multicolumn{2}{c}{Pythia-1.4B} & \\multicolumn{2}{c}{LLaMA-8B} & \\multicolumn{2}{c}{Mistral-7B} \\\\\n\\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\\cmidrule(lr){6-7}\\cmidrule(lr){8-9}\\cmidrule(lr){10-11}\n & AUC & 95\\% CI & AUC & 95\\% CI & AUC & 95\\% CI & AUC & 95\\% CI & AUC & 95\\% CI \\\\\n\\midrule\n0v1 & .9388 & [.929,\\,.949] & .9051 & [.901,\\,.909] & \\textbf{.9592} & [.956,\\,.963] & .9161 & [.912,\\,.920] & .9191 & [.917,\\,.921] \\\\\n1v2 & \\textbf{.7382} & [.709,\\,.767]\\rlap{$^*$} & .7276 & [.722,\\,.733]\\rlap{$^*$} & .5983 & [.593,\\,.603] & \\textbf{.7394} & [.729,\\,.750]\\rlap{$^*$} & .6152 & [.603,\\,.627]\\rlap{$^*$} \\\\\n2v3 & .5300 & [.514,\\,.546] & .5368 & [.522,\\,.551] & .5215 & [.509,\\,.534] & .5112 & [.502,\\,.521] & .5293 & [.520,\\,.538] \\\\\n3v4 & .5022 & [.486,\\,.518] & .5090 & [.504,\\,.515] & .5152 & [.503,\\,.527] & .5200 & [.506,\\,.534] & .5286 & [.518,\\,.539] \\\\\n4v5 & .5219 & [.510,\\,.534] & .5139 & [.501,\\,.527] & .5046 & [.491,\\,.518] & .4996 & [.493,\\,.507] & .5099 & [.504,\\,.516] \\\\\n\\midrule\n$K^*$ & \\multicolumn{2}{c}{\\textbf{2}} & \\multicolumn{2}{c}{\\textbf{2}} & \\multicolumn{2}{c}{1} & \\multicolumn{2}{c}{\\textbf{2}} & \\multicolumn{2}{c}{\\textbf{2}} \\\\\n\\bottomrule\n\\multicolumn{11}{@{}p{\\linewidth}@{}}{\\footnotesize $^*$Permutation $p < 0.001$. $K^*$: max $k$ where $k$v$(k{+}1)$ CI lower bound $> \\theta = 0.60$ (Eq.~\\ref{eq:kstar}).}\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Cross-scorer validation (Code domain).}\nTo rule out scorer confound for Code $\\Kempirical{=}2$, we re-evaluate Qwen2.5-1.5B code generations using Pythia-1.4B as the reference scorer (Table~\\ref{tab:code_crossscorer}).\nCross-family scoring yields $\\Kempirical{=}2$ (1v2 $\\auc = 0.7197$, five-fold minimum $= 0.6985$, all folds above $\\theta$), a decrease of only 1.9\\,pp from Qwen self-scoring ($0.7382$).\nThis contrasts with Wikipedia, where same-family scoring inflates $\\Kempirical$ from 1 to 2 (Appendix~\\ref{sec:wiki_domain}): Code depth signal is robust to scorer choice, while Wikipedia's marginal signal is scorer-sensitive.\nThe scorer confound is therefore domain-specific rather than systematic.\n\n\\begin{table}[htbp]\n\\centering\n\\small\n\\caption{Code domain cross-scorer validation: Pythia-1.4B scorer on Qwen2.5-1.5B code generations. $\\Kempirical{=}2$ is preserved; five-fold minimum 1v2 $\\auc = 0.6985$, well above $\\theta{=}0.60$.}\n\\label{tab:code_crossscorer}\n\\begin{tabular}{lcc}\n\\toprule\nScorer & 1v2 $\\auc$ & 5-fold min \\\\\n\\midrule\nQwen2.5-1.5B (self) & 0.7382 & 0.7093 \\\\\nPythia-1.4B (cross) & 0.7197 & 0.6985 \\\\\n\\midrule\n$\\Delta$ & \\multicolumn{2}{c}{$-1.9$\\,pp} \\\\\n$\\Kempirical$ & \\multicolumn{2}{c}{2 (both)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Borderline Feature Analysis}\n\\label{sec:borderline_analysis}\n\nTo understand why Mistral-7B yields $\\Kempirical{=}1$ while other C4 models yield $\\Kempirical{=}2$, we compute per-feature Cohen's $d$ (depth-1 vs.\\ depth-2) and LightGBM feature importances across six C4 configurations spanning the full 1v2 AUC range (0.594--0.884).\n\nMistral-7B exhibits the lowest depth-0 mean surprisal (2.32 vs.\\ 2.90--3.02 for other models), the scorer model therefore already finds Mistral's output highly predictable.\nThis compressed baseline limits the dynamic range available for detecting inter-generational degradation: all 15 Cohen's $d$ values are weak ($\\bar{|d|} = 0.112$; Table~\\ref{tab:cohens_d_full}), and no single feature exceeds 13\\% of total classifier importance.\nThe borderline models (LLaMA-8B, Pythia at $T{=}1.2$) show a similar pattern at slightly higher effect sizes.\n\nGreedy decoding is qualitatively distinct: Pythia-greedy achieves 0.884 AUC via lexical collapse (hapax ratio $d = -1.056$, capturing 47\\% of importance), a signal absent under sampling-based generation where all non-greedy models rely on surprisal variability features.\n\n\\begin{table*}[htbp]\n\\centering\n\\small\n\\caption{Feature-level summary of C4 1v2 classification across model categories. Imp.\\ = normalized LightGBM gain importance (\\%). $\\bar{|d|}$ = mean absolute Cohen's $d$ over all 15 features. $\\Delta\\text{surp}_{1\\to2}$: change in mean surprisal from depth 1 to depth 2.}\n\\label{tab:borderline_features}\n\\begin{tabular}{@{}llc lcc@{}}\n\\toprule\nCategory & Model & AUC & Top-3 Features (Imp.\\%) & $\\bar{|d|}$ & $\\Delta\\text{surp}_{1\\to2}$ \\\\\n\\midrule\nStrong & Pythia-greedy & 0.884 & hapax\\_ratio (47), surp\\_mean (11), low\\_freq\\_ratio (8) & 0.365 & $-$0.160 \\\\\nStrong & Pythia-nuc09 & 0.677 & surp\\_std (20), freq\\_entropy (11), surp\\_d1\\_std (8) & 0.170 & $-$0.196 \\\\\nStrong & Qwen-1.5B-base & 0.626 & surp\\_std (13), freq\\_entropy (10), surp\\_mean (9) & 0.125 & $-$0.159 \\\\\n\\midrule\nBorderline & Pythia-$T{=}1.2$ & 0.617 & surp\\_std (15), freq\\_entropy (10), surp\\_kurt (8) & 0.112 & $-$0.059 \\\\\nBorderline & LLaMA-3.1-8B & 0.612 & surp\\_std (12), surp\\_d1\\_std (10), freq\\_entropy (9) & 0.137 & $-$0.215 \\\\\n\\midrule\nBelow $\\theta$ & Mistral-7B & 0.594 & surp\\_std (13), freq\\_entropy (9), surp\\_d1\\_skew (9) & 0.112 & $-$0.086 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[htbp]\n\\centering\n\\scriptsize\n\\caption{Cohen's $d$ (depth-1 vs.\\ depth-2) for all 15 features across six C4 models. \\textbf{Bold}: largest $|d|$ in each row. Greedy decoding produces qualitatively different effect sizes via lexical collapse (hapax\\_ratio, low\\_freq\\_ratio); under sampling, surprisal variability features (surp\\_std, surp\\_d1\\_std, surp\\_d2\\_std) carry the dominant signal.}\n\\label{tab:cohens_d_full}\n\\begin{tabular}{@{}lrrrrrr@{}}\n\\toprule\nFeature & \\rotatebox{60}{Pythia-greedy} & \\rotatebox{60}{Pythia-nuc09} & \\rotatebox{60}{Qwen-1.5B-base} & \\rotatebox{60}{Pythia-$T{=}1.2$} & \\rotatebox{60}{LLaMA-3.1-8B} & \\rotatebox{60}{Mistral-7B} \\\\",
      "numLines": 300,
      "startLine": 600,
      "totalLines": 1090
    }
  },
  "sourceToolAssistantUUID": "3520a540-25a9-469b-8895-4c2ffa51b41f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 64_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "05987c5d-e85f-4aa9-8d15-53e093342c14",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 65_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Assistant

_source line 66 · 2026-05-21T06:35:18.491Z_

<details><summary>Logged reasoning block</summary>

```text
I've now read the vast majority of the paper's content. Let me also scan for em-dashes and other AI-style markers.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "05987c5d-e85f-4aa9-8d15-53e093342c14",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "0b425e64-ec6f-4c71-9e9c-8434acd855c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 67 · 2026-05-21T06:35:19.019Z_

扫描 AI 风格标记和其他具体模式。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0b425e64-ec6f-4c71-9e9c-8434acd855c2",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "957e4e69-da79-42f8-b5e3-6f1fd788b14b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 68 · 2026-05-21T06:35:21.397Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01F8LXX2BjnF8LwZhkVgNeLV`</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "957e4e69-da79-42f8-b5e3-6f1fd788b14b",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "fae6340e-2039-40c9-8099-89d1803b3102",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 69 · 2026-05-21T06:35:27.936Z_

<details><summary>↩ Tool result · `toolu_01Sc28WTYFUemjUswhsdXaA7`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d922142d-298c-4b75-9cce-e390779fcc3b",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "ad46ee55-94f2-492f-9014-25f893a17bc8",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "d922142d-298c-4b75-9cce-e390779fcc3b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 70 · 2026-05-21T06:35:21.433Z_

<details><summary>↩ Tool result · `toolu_01F8LXX2BjnF8LwZhkVgNeLV`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fae6340e-2039-40c9-8099-89d1803b3102",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "e0be2e1e-8ff9-43c0-af7f-667769beceb6",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "fae6340e-2039-40c9-8099-89d1803b3102",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 71 · 2026-05-21T06:35:22.354Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01B2EdYETMV2vRXSnqxQdQ4s`</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e0be2e1e-8ff9-43c0-af7f-667769beceb6",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "8a415e03-f0b9-4947-b1d4-e34af27b7b99",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 72 · 2026-05-21T06:35:22.372Z_

<details><summary>↩ Tool result · `toolu_01B2EdYETMV2vRXSnqxQdQ4s`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8a415e03-f0b9-4947-b1d4-e34af27b7b99",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "2859dcb9-a06a-46c3-9eb9-a28ecdd118f2",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "8a415e03-f0b9-4947-b1d4-e34af27b7b99",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 73 · 2026-05-21T06:35:23.838Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01UDGpLtyzN7GhZDTtiWdQwa`</summary>

```json
{
  "pattern": "(it is worth noting|notably|importantly|it should be noted|it is important to note)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
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
  "parentUuid": "2859dcb9-a06a-46c3-9eb9-a28ecdd118f2",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "a3053353-4ffb-4146-a12c-7fec6fd29b3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 74 · 2026-05-21T06:35:23.894Z_

<details><summary>↩ Tool result · `toolu_01UDGpLtyzN7GhZDTtiWdQwa`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:78:Notably, the most marginal self-scored configuration (Qwen-cont, CI lower $= 0.602$, margin $0.2$\,pp) drops to $\Kempirical{=}1$ under Pythia and OLMo scoring (1v2 AUC $= 0.592$/$0.586$), reducing the continuation-mode count from 7/9 to 6/9 under strict cross-scorer control.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a3053353-4ffb-4146-a12c-7fec6fd29b3f",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "90e4f566-72fa-4c77-9224-01f2243d7cff",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:78:Notably, the most marginal self-scored configuration (Qwen-cont, CI lower $= 0.602$, margin $0.2$\\,pp) drops to $\\Kempirical{=}1$ under Pythia and OLMo scoring (1v2 AUC $= 0.592$/$0.586$), reducing the continuation-mode count from 7/9 to 6/9 under strict cross-scorer control.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "a3053353-4ffb-4146-a12c-7fec6fd29b3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 75 · 2026-05-21T06:35:25.721Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01LCFy5aixMVEtYcR8E8cC3c`</summary>

```json
{
  "pattern": "(delve|leverage|utilize|facilitate|a myriad|a plethora|in the realm of)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
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
  "parentUuid": "90e4f566-72fa-4c77-9224-01f2243d7cff",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "2cee309d-e7e4-4c95-8708-76e88573facb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 76 · 2026-05-21T06:35:25.736Z_

<details><summary>↩ Tool result · `toolu_01LCFy5aixMVEtYcR8E8cC3c`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2cee309d-e7e4-4c95-8708-76e88573facb",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "40e905e6-09a0-41e8-be6f-5198acd97324",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "2cee309d-e7e4-4c95-8708-76e88573facb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 77 · 2026-05-21T06:35:27.176Z_

<details open><summary>🔧 Tool call — Grep · `toolu_016VUDkTL84sm4GmHtGUzDY1`</summary>

```json
{
  "pattern": ", (demonstrating|highlighting|suggesting|indicating|showcasing|underscoring|revealing)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "40e905e6-09a0-41e8-be6f-5198acd97324",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "eb200a50-0dec-41f1-8cb0-9bc7a62d315f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 78 · 2026-05-21T06:35:27.190Z_

<details><summary>↩ Tool result · `toolu_016VUDkTL84sm4GmHtGUzDY1`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex:12:Wang et al.~\cite{wang2025attractor} show that successive paraphrasing converges to low-period attractor cycles, suggesting a dynamical-systems view; the attractor entry depth may correspond to the discrimination boundary, though this parallel remains suggestive.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:17:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:405:Cross-transfer generally reduces $\Kempirical$ by approximately one level: in-distribution $\Kempirical{=}3$ models (Pythia, Qwen-7B, LLaMA-8B, Mistral-7B) drop to $\Kempirical{=}2$ in most off-diagonal pairs, indicating that roughly one depth level of discriminability is model-specific.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:406:The sole cross-transfer pair preserving $\Kempirical{=}3$ is Pythia$\to$Qwen-7B (2v3 $\auc = 0.610$, CI lower $= 0.602$), suggesting Pythia learns the most transferable depth features.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:497:\caption{Retrain-chain AUC decay across 7 generation pairs (Qwen2.5-1.5B LoRA). Unlike prompt-chain (sharp cliff at 0v1$\to$1v2), retrain-chain AUC decays gradually from 0.984 to 0.641, with all pairs above $\theta{=}0.60$. Error bars: 95\% CI from 5-fold CV. Dashed line: $\theta{=}0.60$; extrapolated 7v8 $\approx 0.57$ (below $\theta$), suggesting $\Kempirical{=}7$ is near the ceiling.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:980:The F1-based boundary coincides with the AUC CI-based $\Kempirical$ for all configurations, indicating that the discrimination boundary is robust to the choice of evaluation metric.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:74:The 15D features yield a feature-set-specific lower bound; DeBERTa extends $\Kempirical$ by $+1$--$2$ on structured domains, suggesting headroom remains.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:76:The filtering evaluation validates on two architectures with small effect sizes (max $+$1.92\,pp), demonstrating strategy ordering rather than large absolute gains.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex:33:The progression 15D $\to$ neural probes ($K^*_{\text{neural}}{=}3$) $\to$ DeBERTa ($\Kempirical{=}4$) shows diminishing returns, suggesting $K^*_\text{theory} \approx 3$--$4$; permutation importance confirms saturation at 2v3 (Appendix~\ref{sec:feature_importance}).
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:383:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex:31:  Zero-shot frontier LLMs likewise collapse beyond $\Kempirical$: per-depth recall at depths $\geq 2$ ranges from 8--38\% (vs.\ 20\% chance), indicating error redistribution rather than genuine depth recovery (Section~\ref{sec:why_kstar}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "eb200a50-0dec-41f1-8cb0-9bc7a62d315f",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "5cd14aff-abda-4acc-8860-0d34412f1c92",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex:12:Wang et al.~\\cite{wang2025attractor} show that successive paraphrasing converges to low-period attractor cycles, suggesting a dynamical-systems view; the attractor entry depth may correspond to the discrimination boundary, though this parallel remains suggestive.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:17:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:405:Cross-transfer generally reduces $\\Kempirical$ by approximately one level: in-distribution $\\Kempirical{=}3$ models (Pythia, Qwen-7B, LLaMA-8B, Mistral-7B) drop to $\\Kempirical{=}2$ in most off-diagonal pairs, indicating that roughly one depth level of discriminability is model-specific.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:406:The sole cross-transfer pair preserving $\\Kempirical{=}3$ is Pythia$\\to$Qwen-7B (2v3 $\\auc = 0.610$, CI lower $= 0.602$), suggesting Pythia learns the most transferable depth features.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:497:\\caption{Retrain-chain AUC decay across 7 generation pairs (Qwen2.5-1.5B LoRA). Unlike prompt-chain (sharp cliff at 0v1$\\to$1v2), retrain-chain AUC decays gradually from 0.984 to 0.641, with all pairs above $\\theta{=}0.60$. Error bars: 95\\% CI from 5-fold CV. Dashed line: $\\theta{=}0.60$; extrapolated 7v8 $\\approx 0.57$ (below $\\theta$), suggesting $\\Kempirical{=}7$ is near the ceiling.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:980:The F1-based boundary coincides with the AUC CI-based $\\Kempirical$ for all configurations, indicating that the discrimination boundary is robust to the choice of evaluation metric.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:74:The 15D features yield a feature-set-specific lower bound; DeBERTa extends $\\Kempirical$ by $+1$--$2$ on structured domains, suggesting headroom remains.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:76:The filtering evaluation validates on two architectures with small effect sizes (max $+$1.92\\,pp), demonstrating strategy ordering rather than large absolute gains.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex:33:The progression 15D $\\to$ neural probes ($K^*_{\\text{neural}}{=}3$) $\\to$ DeBERTa ($\\Kempirical{=}4$) shows diminishing returns, suggesting $K^*_\\text{theory} \\approx 3$--$4$; permutation importance confirms saturation at 2v3 (Appendix~\\ref{sec:feature_importance}).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:383:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex:31:  Zero-shot frontier LLMs likewise collapse beyond $\\Kempirical$: per-depth recall at depths $\\geq 2$ ranges from 8--38\\% (vs.\\ 20\\% chance), indicating error redistribution rather than genuine depth recovery (Section~\\ref{sec:why_kstar}).",
    "numLines": 11
  },
  "sourceToolAssistantUUID": "eb200a50-0dec-41f1-8cb0-9bc7a62d315f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 79 · 2026-05-21T06:35:27.919Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Sc28WTYFUemjUswhsdXaA7`</summary>

```json
{
  "pattern": "(Furthermore|Moreover|Additionally),",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5cd14aff-abda-4acc-8860-0d34412f1c92",
  "isSidechain": false,
  "requestId": "req_011CbFFSSMrjGDXnzQq89jhg",
  "type": "assistant",
  "uuid": "d922142d-298c-4b75-9cce-e390779fcc3b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tt4oej2R7LAoTUi8bMThtF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10176,
      "cache_read_input_tokens": 99981,
      "output_tokens": 902,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10176,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 902,
          "cache_read_input_tokens": 99981,
          "cache_creation_input_tokens": 10176,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10176
          },
          "type": "message"
        }
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

_source line 80 · 2026-05-21T06:35:27.986Z_

```json
{
  "parentUuid": "ad46ee55-94f2-492f-9014-25f893a17bc8",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "8f1beeca-ea8e-4c31-854c-a8794ae492a7",
  "timestamp": "2026-05-21T06:35:27.986Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 81 · 2026-05-21T06:35:33.269Z_

<details><summary>Logged reasoning block</summary>

```text
Let me also check for other patterns and do a few more searches for the audit.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8f1beeca-ea8e-4c31-854c-a8794ae492a7",
  "isSidechain": false,
  "requestId": "req_011CbFFTSYYh7pENq1GP95us",
  "type": "assistant",
  "uuid": "c77a6ad9-35bb-4bc4-97af-de02756802e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017mtV5DpYuLkPHKp1Fvbsiy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2472,
      "cache_read_input_tokens": 110157,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2472,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 110157,
          "cache_creation_input_tokens": 2472,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2472
          },
          "type": "message"
        }
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

_source line 82 · 2026-05-21T06:35:33.895Z_

检查更多模式：占位符、统计检验支撑、标题范围词匹配。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c77a6ad9-35bb-4bc4-97af-de02756802e2",
  "isSidechain": false,
  "requestId": "req_011CbFFTSYYh7pENq1GP95us",
  "type": "assistant",
  "uuid": "ae7723b6-f2e4-43f3-8f54-e4e778591e27",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017mtV5DpYuLkPHKp1Fvbsiy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2472,
      "cache_read_input_tokens": 110157,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2472,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 110157,
          "cache_creation_input_tokens": 2472,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2472
          },
          "type": "message"
        }
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

_source line 83 · 2026-05-21T06:35:35.673Z_

<details open><summary>🔧 Tool call — Grep · `toolu_011mZkpx5FB25BSuF3Hiykd5`</summary>

```json
{
  "pattern": "(TODO|TBD|PLACEHOLDER|XX\\.XX|\\[If |FIXME)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ae7723b6-f2e4-43f3-8f54-e4e778591e27",
  "isSidechain": false,
  "requestId": "req_011CbFFTSYYh7pENq1GP95us",
  "type": "assistant",
  "uuid": "43c9fe18-2b9b-4368-9938-d2a76e826865",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017mtV5DpYuLkPHKp1Fvbsiy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2472,
      "cache_read_input_tokens": 110157,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2472,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 110157,
          "cache_creation_input_tokens": 2472,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2472
          },
          "type": "message"
        }
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

_source line 84 · 2026-05-21T06:35:42.160Z_

<details><summary>↩ Tool result · `toolu_019mC8pyMnkM1AN4uGmbKKUd`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex:1:\section{Related Work}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c3.tex:1:\section{Consistency Check: $\Kempirical$-Guided Filtering}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:1:\section{Extended Analysis and Limitations}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:68:\section*{Limitations}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:80:\section*{Ethics Statement}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/conclusion.tex:1:\section{Conclusion}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:1:\section{Experiments}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex:1:\section{Discussion}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex:1:\section{Method}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:2:\section{Notation}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:29:\section{Supplementary Figures}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:46:\section{Supplementary Tables}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex:1:\section{Introduction}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "549c4b89-aab8-4cb2-a355-81ed47a6ca14",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "201104cf-c959-4b1f-99fb-c6c380129ffb",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex:1:\\section{Related Work}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c3.tex:1:\\section{Consistency Check: $\\Kempirical$-Guided Filtering}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:1:\\section{Extended Analysis and Limitations}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:68:\\section*{Limitations}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex:80:\\section*{Ethics Statement}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/conclusion.tex:1:\\section{Conclusion}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:1:\\section{Experiments}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/discussion.tex:1:\\section{Discussion}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex:1:\\section{Method}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:2:\\section{Notation}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:29:\\section{Supplementary Figures}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex:46:\\section{Supplementary Tables}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex:1:\\section{Introduction}",
    "numLines": 13
  },
  "sourceToolAssistantUUID": "549c4b89-aab8-4cb2-a355-81ed47a6ca14",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 85 · 2026-05-21T06:35:35.696Z_

<details><summary>↩ Tool result · `toolu_011mZkpx5FB25BSuF3Hiykd5`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "43c9fe18-2b9b-4368-9938-d2a76e826865",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "0805dfd4-bf9e-4bdd-95db-d1e96d3148f3",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "43c9fe18-2b9b-4368-9938-d2a76e826865",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 86 · 2026-05-21T06:35:36.510Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01EYHjjj2JukUBWJtQasHNKe`</summary>

```json
{
  "pattern": "significantly",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0805dfd4-bf9e-4bdd-95db-d1e96d3148f3",
  "isSidechain": false,
  "requestId": "req_011CbFFTSYYh7pENq1GP95us",
  "type": "assistant",
  "uuid": "e5345667-ce1f-48ea-983d-77f73919b4dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017mtV5DpYuLkPHKp1Fvbsiy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2472,
      "cache_read_input_tokens": 110157,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2472,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 110157,
          "cache_creation_input_tokens": 2472,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2472
          },
          "type": "message"
        }
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

_source line 87 · 2026-05-21T06:35:36.527Z_

<details><summary>↩ Tool result · `toolu_01EYHjjj2JukUBWJtQasHNKe`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:123:Binary-ours significantly outperforms all alternatives on MMLU ($p_{\text{corr}} \leq 0.021$); Graduated$_{0.9}$ is indistinguishable on HellaSwag ($p = 1.00$) but worse on MMLU ($p_{\text{corr}} = 0.011$).
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:620:For LLaMA-8B on C4, all three baselines significantly outperform OBD ($p \leq 0.001$), likely reflecting LightGBM overfitting on the relatively noisy 8B-generated features rather than a systematic classifier advantage.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e5345667-ce1f-48ea-983d-77f73919b4dd",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "4507c54b-acfd-457a-9dac-695ac32aeb9d",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:123:Binary-ours significantly outperforms all alternatives on MMLU ($p_{\\text{corr}} \\leq 0.021$); Graduated$_{0.9}$ is indistinguishable on HellaSwag ($p = 1.00$) but worse on MMLU ($p_{\\text{corr}} = 0.011$).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:620:For LLaMA-8B on C4, all three baselines significantly outperform OBD ($p \\leq 0.001$), likely reflecting LightGBM overfitting on the relatively noisy 8B-generated features rather than a systematic classifier advantage.",
    "numLines": 2
  },
  "sourceToolAssistantUUID": "e5345667-ce1f-48ea-983d-77f73919b4dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 88 · 2026-05-21T06:35:41.415Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01MCJaWjVVDFoWH5P29RC9Ls`</summary>

```json
{
  "pattern": "state-of-the-art|SOTA",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
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
  "parentUuid": "4507c54b-acfd-457a-9dac-695ac32aeb9d",
  "isSidechain": false,
  "requestId": "req_011CbFFTSYYh7pENq1GP95us",
  "type": "assistant",
  "uuid": "138b3045-5f46-49e9-a3a3-91609e96140a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017mtV5DpYuLkPHKp1Fvbsiy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2472,
      "cache_read_input_tokens": 110157,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2472,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 110157,
          "cache_creation_input_tokens": 2472,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2472
          },
          "type": "message"
        }
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

_source line 89 · 2026-05-21T06:35:41.434Z_

<details><summary>↩ Tool result · `toolu_01MCJaWjVVDFoWH5P29RC9Ls`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "138b3045-5f46-49e9-a3a3-91609e96140a",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "0dc133c6-09f2-4273-b727-17dc8fcb5ec3",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "138b3045-5f46-49e9-a3a3-91609e96140a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 90 · 2026-05-21T06:35:42.140Z_

<details open><summary>🔧 Tool call — Grep · `toolu_019mC8pyMnkM1AN4uGmbKKUd`</summary>

```json
{
  "pattern": "\\\\section\\*?\\{",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0dc133c6-09f2-4273-b727-17dc8fcb5ec3",
  "isSidechain": false,
  "requestId": "req_011CbFFTSYYh7pENq1GP95us",
  "type": "assistant",
  "uuid": "549c4b89-aab8-4cb2-a355-81ed47a6ca14",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017mtV5DpYuLkPHKp1Fvbsiy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2472,
      "cache_read_input_tokens": 110157,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2472,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 110157,
          "cache_creation_input_tokens": 2472,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2472
          },
          "type": "message"
        }
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

_source line 91_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "201104cf-c959-4b1f-99fb-c6c380129ffb",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 92_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Tool call

_source line 93 · 2026-05-21T06:35:46.570Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Rg9yM11NfhYunq2qHNW9W5`</summary>

```json
{
  "pattern": "\\\\Kempirical|\\\\Kstar",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "201104cf-c959-4b1f-99fb-c6c380129ffb",
  "isSidechain": false,
  "requestId": "req_011CbFFUVrm1eQLzCpDAUAku",
  "type": "assistant",
  "uuid": "6b767012-98dc-47a2-a8ba-057ab21e95a5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015z5K1iuNxnLyUWUEqt4iyG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1570,
      "cache_read_input_tokens": 112629,
      "output_tokens": 270,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1570,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 270,
          "cache_read_input_tokens": 112629,
          "cache_creation_input_tokens": 1570,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1570
          },
          "type": "message"
        }
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

_source line 94 · 2026-05-21T06:35:46.587Z_

<details><summary>↩ Tool result · `toolu_01Rg9yM11NfhYunq2qHNW9W5`</summary>

```text
22:\newcommand{\Kstar}{{K^*}}
23:\newcommand{\Kempirical}{{K^*}}
39:We measure the discrimination boundary $\Kempirical$, defined as the maximum depth at which adjacent generations remain statistically distinguishable, under prompt-chain generation using largely generator-invariant statistical features and an ordinal classifier.
40:The $\theta$-invariant domain ordering arXiv ($\Kempirical{=}3$) $>$ C4 ($\Kempirical{=}2$) $=$ Code ($\Kempirical{=}2$) $>$ Wikipedia ($\Kempirical{=}1$) holds across six architecture families ($\leq$14B); within this hierarchy, $\Kempirical{=}2$ at $\theta{=}0.60$ for web text emerges as the dominant mode (four of six families; changepoint-confirmed).
41:The domain ordering is feature-set invariant (preserved under both 15D statistics and DeBERTa fine-tuning), while absolute $\Kempirical$ values are feature-dependent: DeBERTa matches the 15D bound on C4 and Code but extends $\Kempirical$ to 3 on Wikipedia and 4 on arXiv, placing 15D measurements as conservative lower bounds.
42:Multi-source pooling preserves domain-calibrated $\Kempirical$ across all four domains with negligible generator-identity signal; features transfer across generators (80--92\% aggregate accuracy, driven by high 0v1 separability), but boundary-level $\Kempirical$ assignments fail under cross-model transfer (4/6 off-diagonal 7B pairs fall below $\theta$).
43:As a consistency check, $\Kempirical{=}2$ correctly predicts that binary filtering outperforms graduated alternatives for web text.
70:All experiments are conducted at $\leq$14B scale (6 architecture families, 10 configurations) with English text across four domains and four decoding strategies; whether $\Kempirical{=}2$ holds at 70B+ scales remains unverified.
71:Main results use prompt-chain only, isolating text-intrinsic degradation; retrain-chain yields $\Kempirical{=}7$ (Appendix~\ref{sec:extended_limitations}), and mixed-chain scenarios are not addressed.
72:Cross-model transfer retains 80--92\% aggregate accuracy but boundary-level $\Kempirical$ assignments remain fragile (4/6 off-diagonal 7B pairs fall below $\theta$; Section~\ref{sec:transfer}).
74:The 15D features yield a feature-set-specific lower bound; DeBERTa extends $\Kempirical$ by $+1$--$2$ on structured domains, suggesting headroom remains.
75:$\Kempirical$ is $\theta$-dependent (ranges from 2--3 at $\theta{=}0.55$ to 1 at $\theta{=}0.70$), though a $\theta$-free changepoint analysis agrees within $\pm 1$ for 35/37 configurations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6b767012-98dc-47a2-a8ba-057ab21e95a5",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "c687b473-9382-47e4-b96f-cef6c1807dcb",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "22:\\newcommand{\\Kstar}{{K^*}}\n23:\\newcommand{\\Kempirical}{{K^*}}\n39:We measure the discrimination boundary $\\Kempirical$, defined as the maximum depth at which adjacent generations remain statistically distinguishable, under prompt-chain generation using largely generator-invariant statistical features and an ordinal classifier.\n40:The $\\theta$-invariant domain ordering arXiv ($\\Kempirical{=}3$) $>$ C4 ($\\Kempirical{=}2$) $=$ Code ($\\Kempirical{=}2$) $>$ Wikipedia ($\\Kempirical{=}1$) holds across six architecture families ($\\leq$14B); within this hierarchy, $\\Kempirical{=}2$ at $\\theta{=}0.60$ for web text emerges as the dominant mode (four of six families; changepoint-confirmed).\n41:The domain ordering is feature-set invariant (preserved under both 15D statistics and DeBERTa fine-tuning), while absolute $\\Kempirical$ values are feature-dependent: DeBERTa matches the 15D bound on C4 and Code but extends $\\Kempirical$ to 3 on Wikipedia and 4 on arXiv, placing 15D measurements as conservative lower bounds.\n42:Multi-source pooling preserves domain-calibrated $\\Kempirical$ across all four domains with negligible generator-identity signal; features transfer across generators (80--92\\% aggregate accuracy, driven by high 0v1 separability), but boundary-level $\\Kempirical$ assignments fail under cross-model transfer (4/6 off-diagonal 7B pairs fall below $\\theta$).\n43:As a consistency check, $\\Kempirical{=}2$ correctly predicts that binary filtering outperforms graduated alternatives for web text.\n70:All experiments are conducted at $\\leq$14B scale (6 architecture families, 10 configurations) with English text across four domains and four decoding strategies; whether $\\Kempirical{=}2$ holds at 70B+ scales remains unverified.\n71:Main results use prompt-chain only, isolating text-intrinsic degradation; retrain-chain yields $\\Kempirical{=}7$ (Appendix~\\ref{sec:extended_limitations}), and mixed-chain scenarios are not addressed.\n72:Cross-model transfer retains 80--92\\% aggregate accuracy but boundary-level $\\Kempirical$ assignments remain fragile (4/6 off-diagonal 7B pairs fall below $\\theta$; Section~\\ref{sec:transfer}).\n74:The 15D features yield a feature-set-specific lower bound; DeBERTa extends $\\Kempirical$ by $+1$--$2$ on structured domains, suggesting headroom remains.\n75:$\\Kempirical$ is $\\theta$-dependent (ranges from 2--3 at $\\theta{=}0.55$ to 1 at $\\theta{=}0.70$), though a $\\theta$-free changepoint analysis agrees within $\\pm 1$ for 35/37 configurations.",
    "numLines": 12
  },
  "sourceToolAssistantUUID": "6b767012-98dc-47a2-a8ba-057ab21e95a5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 95 · 2026-05-21T06:35:47.509Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01BVXSaoK9veX3TtxBFA9FU2`</summary>

```json
{
  "pattern": "consistently",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex",
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c687b473-9382-47e4-b96f-cef6c1807dcb",
  "isSidechain": false,
  "requestId": "req_011CbFFUVrm1eQLzCpDAUAku",
  "type": "assistant",
  "uuid": "da2c5afd-839e-4b48-bb46-6cd457745b3c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015z5K1iuNxnLyUWUEqt4iyG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1570,
      "cache_read_input_tokens": 112629,
      "output_tokens": 270,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1570,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 270,
          "cache_read_input_tokens": 112629,
          "cache_creation_input_tokens": 1570,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1570
          },
          "type": "message"
        }
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

_source line 96 · 2026-05-21T06:35:47.529Z_

<details><summary>↩ Tool result · `toolu_01BVXSaoK9veX3TtxBFA9FU2`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:152:Binary filtering consistently improves over no-filter, with HellaSwag differences significant across all ratios ($p \leq 0.004$, Holm-Bonferroni corrected).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "da2c5afd-839e-4b48-bb46-6cd457745b3c",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "2776b445-c991-4063-835a-eba714c14a49",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex:152:Binary filtering consistently improves over no-filter, with HellaSwag differences significant across all ratios ($p \\leq 0.004$, Holm-Bonferroni corrected).",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "da2c5afd-839e-4b48-bb46-6cd457745b3c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 97 · 2026-05-21T06:38:43.364Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive understanding of the paper. Let me conduct the full content audit.

Let me systematically go through each audit dimension:

### 1. 叙事一致性（CRITICAL）

**Abstract的"问题"：**
- Web-scale corpora contaminated by recursive synthetic content, no method estimates generational depth.

**Intro的"问题"：**
- Same: web-scale text increasingly contaminated by synthetic content from earlier synthetic content. Key question: at what generational depth does degradation become undetectable. Binary detectors produce no depth estimate. No method provides per-text operational estimate of generational depth.


- ✅ Abstract problem == Intro problem. Consistent.

**Intro的"贡献列表"：**
The paper presents three main contributions: first, empirical measurements of the critical generation count K* across multiple model configurations, domains, and decoding strategies, showing that multi-source pooling preserves domain-specific K* values while frontier LLMs also experience collapse. Second, they identify a feature-set-invariant domain ordering where arXiv shows the lowest K*, followed by C4 and Code at similar levels, then Wikipedia, though absolute K* values depend on the feature set used. Third, they demonstrate that generator-invariant features achieve 80-92% accuracy in transfer scenarios, but the fragility of boundary-level K* assignments suggests limitations in cross-domain generalization.

The methodology combines K* definition with a threshold parameter θ, LOFO validation, a 15-dimensional feature set, and an OBD-LightGBM classifier across 10 model configurations and 5000 C4 seeds at K=5 depth levels. The experiments systematically validate each contribution: K* measurements consistently stay at or below 2 across configurations, cross-model transfer works as predicted, feature ordering patterns emerge both directly and through neural probes, and K*-guided filtering correctly predicts binary versus graduated filtering outcomes.

Now I'm checking whether the conclusion's claims align with what the experiments actually demonstrated. The paper reports K*=2 for web text across 4 out of 6 families, shows that domain ordering remains invariant to θ, confirms binary filtering is sufficient, and extends the range to [2,7] with retrain-chain methods. I'm also verifying consistency between the abstract's mention of "six architecture families (≤14B)" and the introduction's "10 model configurations (6 architecture families, 1B-14B)" against what the table shows—these all check out. The abstract's claim about "changepoint-confirmed" K*=2 at θ=0.60 needs to match the experimental changepoint analysis, which shows 49% exact agreement rising to 95% within ±1 deviation. There's a real tension here: the abstract claims "changepoint-confirmed" but the experiments show only 49% exact agreement, with 95% agreement only within ±1. The paper itself acknowledges they don't rely on changepoint agreement for determining K*, so calling it "confirmed" in the abstract is misleading about the strength of that validation.

Looking more carefully at what the abstract actually says—"K*=2 at θ=0.60 for web text emerges as the dominant mode (four of six families; changepoint-confirmed)"—it might be narrowly referring just to confirming K*=2 for that specific C4 web text case rather than all 37 configurations. But even then, PELT being "systematically conservative" means it would give K*≤2, not necessarily K*=2, so the confirmation is still weak. This is worth flagging as a clarity issue in the abstract.

The abstract itself is quite dense and technical—reads more like a results summary than a compelling narrative. The significance section is particularly thin, just mentioning that binary filtering outperforms alternatives. That's a minor concern but worth noting.

For the structure, the intro is building properly: first establishing the contamination problem, then highlighting the gap between binary detection and actual depth estimation, and now moving into why no existing method addresses generational depth estimation.

The transition into our method in paragraph 4 feels a bit abrupt though—it jumps from theoretical motivation straight into describing the study without a clear "we propose" moment. The related work section is well-organized thematically with good positioning statements at the end of each paragraph, so that's solid.

Now I'm checking how the contributions align with what's actually delivered in the paper. The first contribution about empirically measuring K* maps to section 4.1 where we show K*≤2 across different configurations, and that's backed up in the tables.  The feature-set-invariant domain ordering shows up in section 4.5 with the cross-domain variation analysis and the domain-specific K* values in table 5. The transfer and consistency work spans section 4.2 on cross-model transfer, section 5 on filtering, and figure 3 showing the transfer patterns. Everything connects back to the contributions—there aren't any orphaned sections floating around without a clear purpose.

The title captures the core idea about measuring discrimination boundaries in recursive synthetic text across different generational depths. The abstract mentions four source domains and the experiments validate this across all of them, while table 1 confirms the six architecture families being tested. Now I'm checking how strongly the claims are supported by the statistical evidence. The "significantly outperforms" language appears only in the appendix with proper p-values backing it up, and "consistently" is used once with Holm-Bonferroni corrected significance across multiple conditions. The quantitative accuracy claims in the abstract need to match what's actually reported in the experiments. Looking at the experimental rigor, the dose-response table reports mean and standard deviation across five random seeds, and the pairwise AUC tables include 95% confidence intervals from bootstrap resampling. The study compares against established binary detectors and baseline classifiers, and while there are no existing external depth estimation baselines to compare against, this is appropriately framed as the first work in this area. The ablations are thorough—covering feature subsets, self-BLEU independence, LaTeX markup effects, decoding strategies, sequence length, model architecture choices, and cross-scorer validation.

For reproducibility, the hyperparameters, neural probe specifications, data details, and model configurations are all documented in the supplementary tables. GPU requirements and training time aren't explicitly stated, which is a minor gap. The paper includes a Limitations section and Ethics Statement, though the ARR reproducibility checklist may be submitted as a separate form rather than embedded in the paper itself.

Looking at the notation consistency, I notice that `\Kstar` and `\Kempirical` are both aliased to the same symbol `{K^*}`, so they render identically even though they're meant to represent different concepts—the empirical boundary versus the general K* notation. This creates potential confusion since they're used interchangeably in places like the related work section and filtering tables.

Now examining the section transitions, the flow from Introduction through Related Work into Method is a bit abrupt—the Related Work ends with ordinal classification discussion but Method jumps straight into Problem Formulation without a clear bridge. The other transitions work well: Method naturally leads to Experiments, which establish the K*=2 finding that Filtering then validates, and the rest flows smoothly into Discussion and Conclusion.

The Discussion section does more than just report numbers—it offers higher-level interpretation around one-wash laundering, JSD decay regimes, and feature-space ceilings. For limitations, the paper covers six substantive points: scale constraints up to 14B parameters, reliance on prompt-chain methodology, cross-model transfer fragility, feature-set specificity, θ-dependency, and small effect sizes in filtering. The limitations section runs about 150 words across seven sentences, which meets the threshold, though it's on the borderline.

Now I'm checking the writing style for AI-like patterns. Em-dashes and en-dashes are absent, which is good. "Notably" appears once, and while there are several -ing phrase endings scattered through the text like "suggesting," "indicating," and "demonstrating," most feel natural in a technical context—though "demonstrating strategy ordering" in the main text is borderline. The extended limitations in the appendix provide much more detail, and overall the prose avoids evasiveness by grounding claims in specific numbers and conditions.

Looking at the Discussion section structure, it relies heavily on \paragraph{} formatting with each item running 2-4 sentences, which creates some over-segmentation but is fairly standard for results-dense papers. One thing I should verify: the abstract claims Code shows a domain ordering of 2, but checking Table 5 reveals mixed results across different model sizes, so I need to reconcile that discrepancy. B=1, LLaMA-8B=2, Mistral-7B=2. Only 4/5 models yield K*=2. The abstract's unqualified "Code (K*=2)" is technically OK since it's the dominant mode, but it omits the exception.

Also, the abstract says "six architecture families" but Table 5 (domain_kstar) for Code only shows 5 models (Gemma and OLMo have "---"). The abstract's domain ordering claim implicitly covers all 6 families but Code data only exists for 5.

Let me also verify: the intro says "across 10 model configurations (6 architecture families, 1B-14B)". Table 1 (setup) shows exactly 10 configs from 6 families. ✅

One more thing: the Intro contribution (a) mentions "multi-source pooling preserves domain-calibrated K* across all four domains (+0.010 mean AUC for generator identity across four domains)". This specific number (+0.010) appears in Section 4.5 as well. ✅

Now I'm noticing the title might be slightly misleading—it emphasizes "Generational Depth Estimation" but the paper actually characterizes where depth discrimination fails rather than building a practical depth estimator. The subtitle "Measuring the Discrimination Boundary" is more accurate, though the first part could lead readers to expect a depth estimation method. That said, the paper does describe a depth estimation pipeline, so the framing isn't entirely off.

Now I'm checking the abstract claims against the actual results. The DeBERTa numbers check out across domains, though there are some nuances—Code shows K*=2 as the dominant result but not universally across all five models tested, and the "six architecture families" claim doesn't quite align with Code having data for only five of them.

The novelty claim about providing per-text depth estimates with statistical guarantees seems well-supported by the related work survey, which shows existing methods focus on binary detection or distributional metrics rather than depth estimation.

I'm now compiling my findings into critical and warning-level issues.

On the critical side, nothing truly stands out. For warnings, the abstract's use of "changepoint-confirmed" is misleading since the paper explicitly states it doesn't rely on changepoint agreement for determining K*, yet exact agreement is only 49%. The abstract itself is also too dense—it reads like a compressed results section rather than a narrative, cramming specific numbers and domain comparisons into 200 words when it should tell the core story more clearly. There's also a filler "Notably" in the experiments file, some minor -ing phrase patterns in the main text, and the first contribution point runs extremely long across multiple lines.

The contribution item bundles too many distinct claims together—K* measurement, multi-source pooling, and zero-shot LLM failure—when each deserves separate treatment or the whole thing needs tightening. The Limitations section sits right at the minimum threshold around 150 words, and the Discussion reads like disconnected bullet points rather than a flowing narrative since it's composed entirely of short paragraph blocks without connective tissue between them.

At the info level, the semantic macros for K* and K_empirical both render identically, which creates confusion during source-level editing even though the output looks fine. Additionally, critical training details like GPU model, training time, and total compute hours aren't reported anywhere in the main text or appendix.

Some appendix tables are missing confidence intervals—the K* table just shows raw values while the extended versions include them. The zero-shot LLM experiment uses notably smaller sample sizes (N=500 for GPT-5.5, N=499 for Claude Opus 4.6) compared to the main experiments at N=5000, which is acknowledged but not treated as a limitation. Coverage also varies across domains—Code and Wikipedia experiments use fewer models than C4, with some entries marked as missing, yet the abstract's domain ordering claim doesn't account for this gap. I should also verify whether the paper explicitly discusses limitations of the filtering evaluation itself.

Looking at the filtering section, the effect sizes are appropriately contextualized as small (max +1.92pp) and framed as demonstrating strategy ordering rather than absolute improvement, and the conclusion hedges the binary filtering results (Δ ≤ 0.53pp). The Data Processing Inequality discussion is also well-hedged—the intro correctly states it implies monotonic information loss, while the methods section clarifies that DPI motivates the theory but doesn't formally guarantee or bound K*. Now I'm noticing a potential issue with how the contribution claims are scoped: the intro says "four of six families" for K*=2 specifically for C4, and the abstract repeats this, but the experiments show this varies significantly by domain—on arXiv it's actually five out of six. Qwen accounts for 4 of the 10 configurations across different sizes and variants, while the remaining 6 families each contribute one configuration, confirming the count. ✅ I'm also noticing that while the paper frames this as "6 architecture families," the Qwen variants at different scales (1.5B instruct, 1.5B base, 7B, 14B) are really just different versions of the same underlying architecture, which somewhat inflates the breadth claim—though the paper does correctly group them as a single family. ✅ Now checking the introduction structure: it opens with background on recursive contamination and the distinction between prompt-chains versus retrain-chains, then identifies the gap that existing detection methods don't estimate contamination depth, explains why this matters for data curation, and builds toward the theoretical framework.

There's a subtle issue with how the abstract frames the findings versus what the results actually show. The abstract emphasizes "largely generator-invariant statistical features" and claims 80-92% transfer accuracy, but the detailed results reveal that boundary-level assignments are quite fragile—only 2 out of 6 off-diagonal 7B model pairs succeed. The abstract does acknowledge this limitation in the same sentence, but leading with the positive framing of generator-invariance might overstate the robustness given how much the method struggles at the boundaries.

I've also verified that the domain ordering claim (arXiv > C4 = Code > Wikipedia) is consistent across the abstract, introduction, experiments, and discussion sections.

Now I'm checking the DeBERTa comparison table more carefully. It includes results at 1.5B, 14B, and 32B scales, but the paper's main experiments only extend to 14B. The 32B results appear in the DeBERTa comparison table, and I need to verify whether this is properly explained in the caption or if there's a gap in the documentation. The 32B results appear only in the DeBERTa comparison table, not in the main experimental setup, which creates a disclosure gap—the paper claims LightGBM shifts by less than 0.5 percentage points across 1.5B to 32B scales, but never identifies what the 32B generator model actually is or explains why it's only tested with DeBERTa and not included in Table 1's experimental configuration.

More critically, the Limitations section explicitly states "all experiments are conducted at ≤14B scale," which directly contradicts the presence of 32B data in the results. Either the 32B model needs to be added to Table 1 with proper documentation, or the Limitations statement needs to be corrected to reflect the actual experimental scope. I'm checking the domain ordering claims in the abstract against the actual data. Code is listed as K*=2 in the abstract, but when I look at Table 5 and the Code section, Pythia-1.4B shows K*=1 for Code, making it 4 out of 5 models at K*=2 rather than all of them. However, C4 has similar exceptions too (Gemma and Mistral both at K*=1), so the abstract's treatment of both as "dominant mode" results is actually consistent—it's just simplifying to the most common pattern rather than listing every exception.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2776b445-c991-4063-835a-eba714c14a49",
  "isSidechain": false,
  "requestId": "req_011CbFFUtGtmqDtFLj3BAZdn",
  "type": "assistant",
  "uuid": "9896e36c-2a1e-46f1-9c88-ebf189d6a74f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GzZxkBaBbgeUNacwKy4bnn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1173,
      "cache_read_input_tokens": 114199,
      "output_tokens": 8155,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1173,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8155,
          "cache_read_input_tokens": 114199,
          "cache_creation_input_tokens": 1173,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1173
          },
          "type": "message"
        }
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

_source line 98 · 2026-05-21T06:38:43.365Z_

Now let me do final targeted checks on specific claims I noticed.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9896e36c-2a1e-46f1-9c88-ebf189d6a74f",
  "isSidechain": false,
  "requestId": "req_011CbFFUtGtmqDtFLj3BAZdn",
  "type": "assistant",
  "uuid": "1af097af-8c77-4a8f-8562-1445c32a3631",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GzZxkBaBbgeUNacwKy4bnn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1173,
      "cache_read_input_tokens": 114199,
      "output_tokens": 8155,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1173,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8155,
          "cache_read_input_tokens": 114199,
          "cache_creation_input_tokens": 1173,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1173
          },
          "type": "message"
        }
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

_source line 99 · 2026-05-21T06:38:43.367Z_

<details open><summary>🔧 Tool call — Grep · `toolu_012T51W5HMoYcx6BmpvukZok`</summary>

```json
{
  "pattern": "32B",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1af097af-8c77-4a8f-8562-1445c32a3631",
  "isSidechain": false,
  "requestId": "req_011CbFFUtGtmqDtFLj3BAZdn",
  "type": "assistant",
  "uuid": "a8735531-defb-448b-90a0-2e57d906cb6a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GzZxkBaBbgeUNacwKy4bnn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1173,
      "cache_read_input_tokens": 114199,
      "output_tokens": 8155,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1173,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8155,
          "cache_read_input_tokens": 114199,
          "cache_creation_input_tokens": 1173,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1173
          },
          "type": "message"
        }
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

_source line 100 · 2026-05-21T06:38:43.985Z_

<details><summary>↩ Tool result · `toolu_01NsNf4tQ3hfkmnNzYaw5Jbk`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4a64ba49-f5f2-4ed2-91e3-a5043f42c59c",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "88ac255b-0a15-4584-baba-14cd993b9d95",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "4a64ba49-f5f2-4ed2-91e3-a5043f42c59c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 101 · 2026-05-21T06:38:43.386Z_

<details><summary>↩ Tool result · `toolu_012T51W5HMoYcx6BmpvukZok`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:97:DeBERTa-v3-base ordinal classifiers raise 1v2 $\auc$ over LightGBM at all three scales (1.5B: $0.705$ vs.\ $0.626$; 14B: $0.678$ vs.\ $0.621$; 32B: $0.694$ vs.\ $0.618$) yet preserve $\Kempirical{=}2$ (all 2v3 CI lower ${<}\,\theta$; Table~\ref{tab:deberta_comparison}); LightGBM shifts by ${<}\,0.5$\,pp across 1.5B--32B.
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:105:\captionof{table}{DeBERTa-v3-base vs.\ LightGBM on C4 generations at three scales. Both classifiers yield $\Kempirical{=}2$ at 1.5B, 14B, and 32B.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:117:LightGBM (32B)  & .958 & .618 & .545 & .522 & .516 \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:118:DeBERTa (32B)   & .993 & .694 & .594 & .567 & .543 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a8735531-defb-448b-90a0-2e57d906cb6a",
  "isSidechain": false,
  "promptId": "62d70c05-034f-4784-ad39-45dca5a89d00",
  "type": "user",
  "uuid": "64add4a6-ce0d-499a-9a5f-a5976a204c80",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:97:DeBERTa-v3-base ordinal classifiers raise 1v2 $\\auc$ over LightGBM at all three scales (1.5B: $0.705$ vs.\\ $0.626$; 14B: $0.678$ vs.\\ $0.621$; 32B: $0.694$ vs.\\ $0.618$) yet preserve $\\Kempirical{=}2$ (all 2v3 CI lower ${<}\\,\\theta$; Table~\\ref{tab:deberta_comparison}); LightGBM shifts by ${<}\\,0.5$\\,pp across 1.5B--32B.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:105:\\captionof{table}{DeBERTa-v3-base vs.\\ LightGBM on C4 generations at three scales. Both classifiers yield $\\Kempirical{=}2$ at 1.5B, 14B, and 32B.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:117:LightGBM (32B)  & .958 & .618 & .545 & .522 & .516 \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex:118:DeBERTa (32B)   & .993 & .694 & .594 & .567 & .543 \\\\",
    "numLines": 4
  },
  "sourceToolAssistantUUID": "a8735531-defb-448b-90a0-2e57d906cb6a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 102 · 2026-05-21T06:38:43.966Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01NsNf4tQ3hfkmnNzYaw5Jbk`</summary>

```json
{
  "pattern": "Checklist|checklist",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "64add4a6-ce0d-499a-9a5f-a5976a204c80",
  "isSidechain": false,
  "requestId": "req_011CbFFUtGtmqDtFLj3BAZdn",
  "type": "assistant",
  "uuid": "4a64ba49-f5f2-4ed2-91e3-a5043f42c59c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GzZxkBaBbgeUNacwKy4bnn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1173,
      "cache_read_input_tokens": 114199,
      "output_tokens": 8155,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1173,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8155,
          "cache_read_input_tokens": 114199,
          "cache_creation_input_tokens": 1173,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1173
          },
          "type": "message"
        }
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

_source line 103 · 2026-05-21T06:38:44.035Z_

```json
{
  "parentUuid": "88ac255b-0a15-4584-baba-14cd993b9d95",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "2a899a08-e30c-4fb2-add0-7bc74c654f26",
  "timestamp": "2026-05-21T06:38:44.035Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 104_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "2a899a08-e30c-4fb2-add0-7bc74c654f26",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 105_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Assistant

_source line 106 · 2026-05-21T06:39:02.958Z_

<details><summary>Logged reasoning block</summary>

```text
OK, so the 32B model appears in the DeBERTa comparison table (experiments_c1.tex:105-118) but is not identified by name and not in Table 1 (setup). The Limitations section says "All experiments are conducted at ≤14B scale (6 architecture families, 10 configurations)". This directly contradicts the 32B data.

Also, no ARR/EMNLP checklist found in the .tex files. For EMNLP 2026 through ARR, a responsible NLP research checklist is typically required as a separate form, not necessarily in the paper itself. I'll note this as info.
 
Looking at the full Limitations section, it acknowledges several key constraints: the experiments max out at 14B parameters with six architecture families and ten configurations, all using English text across four domains and four decoding strategies, while leaving the question of whether the K* metric holds at 70B+ scales unverified. The main results focus on prompt-chain only to isolate text-intrinsic degradation, though the appendix shows retrain-chain achieves K*=7 and mixed-chain scenarios aren't explored. Cross-model transfer maintains 80-92% aggregate accuracy but the boundary-level K* assignments are fragile, with most off-diagonal 7B pairs falling below the threshold.

The 15D features provide a lower bound specific to that feature set, and DeBERTa extends K* by 1-2 points on structured domains, suggesting room for improvement. K* itself depends on the θ parameter, ranging from 2-3 at θ=0.55 down to 1 at θ=0.70, though a θ-free changepoint analysis agrees within ±1 across most configurations. The filtering evaluation is limited to two architectures with small effect sizes, demonstrating strategy ordering rather than substantial absolute gains.

Now I'm noticing the 32B discrepancy—this is a real inconsistency that needs attention.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2a899a08-e30c-4fb2-add0-7bc74c654f26",
  "isSidechain": false,
  "requestId": "req_011CbFFhtmWwTTWMgjq3EwAr",
  "type": "assistant",
  "uuid": "eaaaaa4f-f674-4ebd-957b-a936271208fb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FKgmrAp6q1BLg9GRpNw8dM",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8767,
      "cache_read_input_tokens": 115372,
      "output_tokens": 3419,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8767,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3419,
          "cache_read_input_tokens": 115372,
          "cache_creation_input_tokens": 8767,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8767
          },
          "type": "message"
        }
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

_source line 107 · 2026-05-21T06:40:05.076Z_

审计完成。以下是结构化 findings。

```
[CONTENT_AUDIT_START]

=== 叙事一致性（CRITICAL 级） ===

- [critical] [叙事一致性] main.tex:70 Limitations 声称 "All experiments are conducted at ≤14B scale (6 architecture families, 10 configurations)"，但 experiments_c1.tex:97/117-118 的 DeBERTa 对比表包含 32B generator 结果（LightGBM 32B: 0v1=.958, 1v2=.618; DeBERTa 32B: 0v1=.993, 1v2=.694）。该 32B generator 模型未在 Table 1 (setup) 中列出、未命名、未描述配置，与 Limitations 的"≤14B"声明直接矛盾。需要：(1) 在 Table 1 补充 32B 配置；(2) 修正 Limitations 的 scale 声明；(3) 注明 32B 模型名称。

- [warning] [叙事一致性] main.tex:40 Abstract 使用 "changepoint-confirmed" 描述 K*=2，但 experiments_c1.tex:51 报告 PELT 精确一致率仅 49% (18/37)，论文明确声称 "We do not rely on changepoint agreement for K* determination"。Abstract 的 "changepoint-confirmed" 措辞会误导审稿人认为有独立的 threshold-free 方法完全确认了 K*=2。建议改为 "changepoint-compatible (95% within ±1)" 或删除。

- [warning] [叙事一致性] Introduction contribution (a) (introduction.tex:30-31) 将三个不同层次的发现捆绑在同一条 contribution 中：(1) K* 的首次测量，(2) multi-source pooling 保持 domain-calibrated K*，(3) zero-shot frontier LLM 在 K* 以上失败。这使得该 contribution 过于庞大（原文约 5 行），建议拆分或将 (3) 合并到 contribution (c) 的 transfer 讨论中。

=== 章节结构 ===

- [warning] [章节结构] Abstract（main.tex:38-44）信息密度过高，在约 200 词内塞入了 domain ordering 具体值、DeBERTa 对比、multi-source pooling、transfer 百分比、filtering 结果。审稿人 30 秒内难以抓住核心 story。建议精简为：问题（1句）→ 方法（1句）→ 核心发现 K*=2 + domain ordering（1-2句）→ 实用意义 filtering（1句），将 DeBERTa/transfer 细节留给正文。

- [info] [章节结构] Discussion（discussion.tex）完全由独立 \paragraph{} 项组成（6 个段落，每段 2-4 句），缺少段落间的过渡句和统一的解释框架。虽然每段信息有价值，但整体读感偏碎片化。建议增加 1-2 句过渡句将"一次洗白"、"JSD 衰减"、"特征空间天花板"串联成连贯叙事。

=== 贡献-范围对齐 ===

- [warning] [贡献-范围] experiments_c1.tex:97-118 引入 32B 实验数据，但 Table 1（method.tex:55-77）仅列出 10 个 ≤14B 配置，Abstract 和 Conclusion 均声称"six architecture families"和"≤14B"。32B 数据的来源模型、family 归属、generation 参数均未披露，形成"孤儿数据"。

- [info] [贡献-范围] Table 5 (domain_kstar, experiments_c1.tex:148-164) Code 列 Gemma-2-2B 和 OLMo-1B 显示 "---"（未测），但 Abstract 的 domain ordering "C4 = Code" 未限定 Code 的 model 覆盖范围（5/7 models 有数据）。建议在 Abstract 或 Experiments 中注明 Code 的 model 覆盖率。

=== Claim 强度匹配 ===

- [info] [Claim强度] appendix_extended.tex:152 使用 "consistently" 描述 binary filtering 在所有 contamination ratio 下优于 no-filter，有 Holm-Bonferroni corrected p≤0.004 支撑，强度匹配。

- [info] [Claim强度] "significantly" 仅出现在 appendix 中且均附 p-value（appendix_extended.tex:123 p_corr≤0.021; appendix_extended.tex:620 p≤0.001），正文未使用，强度控制得当。

=== 实验严谨性 ===

- [info] [实验严谨性] 主结果表（tab_kstar_ci, tab_kstar_ci_extended）均有 bootstrap 95% CI 和 permutation p-values。Filtering 表（tab_filtering_main）有 ±std from 3 seeds。Dose-response 有 5 seeds ± std。覆盖充分。

- [info] [实验严谨性] Ablation 覆盖全面：feature subset (appendix_extended §feature_subset)、self-BLEU independence (§selfbleu_ablation)、LaTeX markup (§latex_ablation)、decoding strategy (Tab S2/S10)、length (Tab S11)、scorer sensitivity (Tab S13)、classifier choice McNemar (§mcnemar_baselines)、DeBERTa vs OBD。与 Method 组件数匹配。

=== 可复现性披露 ===

- [warning] [可复现性] 论文未报告 GPU 型号、总训练/推理时间、总 GPU-hours。LightGBM 超参在 Table S6、neural probe 在 Table S7 有披露，但 feature extraction（对 5000×6 depths × 10 configs 的文本跑 Qwen-1.5B scorer）的计算开销和 DeBERTa fine-tuning 的计算开销未报告。ARR reviewer checklist 通常要求此信息。

- [info] [可复现性] ARR Responsible NLP Research Checklist 未在 .tex 源码中出现。EMNLP 2026 通过 ARR 提交可能要求以单独表格形式提交，不影响论文本身，但建议确认。

=== 符号/术语一致性 ===

- [info] [符号] main.tex:22-23 定义 \Kstar 和 \Kempirical 均展开为 {K^*}（同一渲染结果），源码层面语义不区分。建议将 \Kstar 改为仅在泛指 K* 概念时使用，或统一为单一 macro，避免维护混淆。

- [info] [符号] tab_domain_model_kstar.tex caption 中直接使用 $K^*$ 而非 \Kempirical 或 \Kstar 宏，风格不统一（功能无影响）。

=== 章节过渡与逻辑流 ===

- [info] [过渡] Introduction para 4（introduction.tex:23-26）从 DPI 理论动机直接跳到 "We present an empirical characterization study"，缺少明确的 "In this paper, we..." 过渡句标记本文方法的开始。当前写法使 DPI 讨论和 study 描述混在同一段落中。

=== Limitations 诚实度 ===

- [warning] [Limitations] main.tex:68-77 Limitations 段约 145 词，略低于 150 词最低门槛（borderline）。涵盖 6 个 distinct limitations（scale、chain type、transfer fragility、feature-set dependency、θ-dependency、effect sizes），实质性和诚实度良好，但篇幅可以稍扩展。注意 "≤14B" 声明与 32B 数据矛盾（见叙事一致性 critical）。

=== 去 AI 风格 ===

- [warning] [去AI] experiments_c1.tex:78 "Notably, the most marginal self-scored configuration..." — "Notably" 是典型 AI filler word，建议删除直接陈述。

- [info] [去AI] 正文中出现若干 -ing 分词短语结尾：main.tex:76 "demonstrating strategy ordering rather than large absolute gains"；introduction.tex:31 "indicating error redistribution rather than genuine depth recovery"。数量不多（正文 2 处），但可改写为独立句或用冒号引出。

- [info] [去AI] em-dash (—) 和 en-dash ( – ) 扫描通过：0 处。✅
- [info] [去AI] "Furthermore/Moreover/Additionally" 扫描通过：0 处。✅
- [info] [去AI] "delve/leverage/utilize/facilitate/myriad/plethora" 扫描通过：0 处。✅

[CONTENT_AUDIT_END]
```

**审计摘要**: 1 critical, 6 warning, 12 info。

核心问题是 32B 数据与论文声称的 ≤14B scope 矛盾（critical），以及 Abstract "changepoint-confirmed" 措辞不准确（warning）。论文整体叙事一致性强，Abstract/Intro/Method/Experiments/Conclusion 讲的是同一个故事，贡献与实验一一对应。AI 风格痕迹极少。实验严谨性和统计检验覆盖充分。主要改善空间在 Abstract 信息密度过载和 Discussion 碎片化。

[AUDIT_DONE]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eaaaaa4f-f674-4ebd-957b-a936271208fb",
  "isSidechain": false,
  "requestId": "req_011CbFFhtmWwTTWMgjq3EwAr",
  "type": "assistant",
  "uuid": "9c2f15b6-7820-46bb-bfab-cd5eef9e50fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/.claude/sessions/paper_audit_content_f8dc2c1d",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FKgmrAp6q1BLg9GRpNw8dM",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8767,
      "cache_read_input_tokens": 115372,
      "output_tokens": 3419,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8767,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3419,
          "cache_read_input_tokens": 115372,
          "cache_creation_input_tokens": 8767,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8767
          },
          "type": "message"
        }
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

_source line 108_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：gen-depth-contamination Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 63 warning…",
  "leafUuid": "9c2f15b6-7820-46bb-bfab-cd5eef9e50fe",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

### Runtime record

_source line 109_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for gen-depth-contamination paper",
  "sessionId": "62984386-f345-40e1-a05b-dba4cbd3d2a6"
}
```

---

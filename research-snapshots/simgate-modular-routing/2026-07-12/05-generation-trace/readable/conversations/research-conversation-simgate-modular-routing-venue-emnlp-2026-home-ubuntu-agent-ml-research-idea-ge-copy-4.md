# Research conversation: 项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modul

**Death Avoidance as the Dominant Routing Signal: A Counterfactual Analysis on ScienceWorld (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 66
- **Recorded user turns:** 1
- **Tool calls:** 19
- **Original source:** `logs/chats/exported-trajectories/account-2/6d9a8d29-6528-42b3-9f02-c9d1618fc7dd.jsonl`
- **Structured JSON:** [`2e475eb8be487eb7157b.json`](../../sessions/2e/2e475eb8be487eb7157b.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-21T13:43:30.932Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-21T13:43:30.932Z",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "content": "项目：simgate-modular-routing\nVenue：emnlp-2026\n论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper\n\nPhase 1 确定性检查结果：\n源码检查: passed=True, 0 critical, 15 warning\n一致性检查: 0 critical, 10 warning\n编译: ✅, 页数: 25\n\n请按照你的角色指令执行内容结构审计。"
}
```

---

### Runtime record

_source line 2 · 2026-05-21T13:43:30.938Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-21T13:43:30.938Z",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

## Round 1

64 recorded events

### User

_source line 3 · 2026-05-21T13:43:30.990Z_

项目：simgate-modular-routing
Venue：emnlp-2026
论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper

Phase 1 确定性检查结果：
源码检查: passed=True, 0 critical, 15 warning
一致性检查: 0 critical, 10 warning
编译: ✅, 页数: 25

请按照你的角色指令执行内容结构审计。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "a57eed1e-bb60-49c9-ae91-7a1b6521954f",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-21T13:43:30.990Z_

```json
{
  "parentUuid": "a57eed1e-bb60-49c9-ae91-7a1b6521954f",
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
  "uuid": "ef992383-4a82-4d1d-bb6f-72a8dcd231bd",
  "timestamp": "2026-05-21T13:43:30.990Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-21T13:43:30.990Z_

```json
{
  "parentUuid": "ef992383-4a82-4d1d-bb6f-72a8dcd231bd",
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
  "uuid": "7343dbb1-8c00-4eb7-9695-ffecbf8484d7",
  "timestamp": "2026-05-21T13:43:30.990Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-21T13:43:30.990Z_

```json
{
  "parentUuid": "7343dbb1-8c00-4eb7-9695-ffecbf8484d7",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "619e85cd-854a-444a-b377-c58af4f1cedc",
  "timestamp": "2026-05-21T13:43:30.990Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
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
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Assistant

_source line 8 · 2026-05-21T13:43:36.252Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to execute a content structure audit on a paper. Let me follow the instructions:

1. Read `skills/global/paper-writing-norms.skill.md` and `skills/global/paper-quality-lessons.skill.md` for audit standards
2. Read all `.tex` files in the paper directory
3. Audit across all dimensions
4. Output structured findings

Let me start by reading the two skill files and finding all .tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "619e85cd-854a-444a-b377-c58af4f1cedc",
  "isSidechain": false,
  "requestId": "req_011CbFp6eV9fLrP3KuRYEdfS",
  "type": "assistant",
  "uuid": "e4c782d6-0eab-4ade-8136-69256b7d5362",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013BXfBDr37mv4ysXbeB8cKn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25484,
      "cache_read_input_tokens": 11846,
      "output_tokens": 364,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 364,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25484
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-21T13:43:36.859Z_

开始内容结构审计。先加载审计标准和论文源码。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e4c782d6-0eab-4ade-8136-69256b7d5362",
  "isSidechain": false,
  "requestId": "req_011CbFp6eV9fLrP3KuRYEdfS",
  "type": "assistant",
  "uuid": "934ea496-c97a-424d-a761-cf1299aed5e9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013BXfBDr37mv4ysXbeB8cKn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25484,
      "cache_read_input_tokens": 11846,
      "output_tokens": 364,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 364,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25484
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-21T13:43:37.294Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CKvGV8pxLy2giYi7vkcaWW`</summary>

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
  "parentUuid": "934ea496-c97a-424d-a761-cf1299aed5e9",
  "isSidechain": false,
  "requestId": "req_011CbFp6eV9fLrP3KuRYEdfS",
  "type": "assistant",
  "uuid": "10f48fe3-6b21-4d97-87ba-2184cb300e15",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013BXfBDr37mv4ysXbeB8cKn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25484,
      "cache_read_input_tokens": 11846,
      "output_tokens": 364,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 364,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25484
          },
          "type": "message"
        }
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

_source line 11 · 2026-05-21T13:43:38.735Z_

<details><summary>↩ Tool result · `toolu_015pWA1PnSb7CWUXVc3VGSA4`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f2e8e94e-4554-4bf9-ad4b-89c051eeb308",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "8fe17a6a-a200-45cc-97d9-f329afdf1951",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex",
      "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex"
    ],
    "durationMs": 7,
    "numFiles": 9,
    "truncated": false
  },
  "sourceToolAssistantUUID": "f2e8e94e-4554-4bf9-ad4b-89c051eeb308",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-21T13:43:37.313Z_

<details><summary>↩ Tool result · `toolu_01CKvGV8pxLy2giYi7vkcaWW`</summary>

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
  "parentUuid": "10f48fe3-6b21-4d97-87ba-2184cb300e15",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "952460ab-c23f-475c-a072-5a6f9ad7aed3",
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
  "sourceToolAssistantUUID": "10f48fe3-6b21-4d97-87ba-2184cb300e15",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 13 · 2026-05-21T13:43:37.819Z_

<details open><summary>🔧 Tool call — Read · `toolu_017SXrMWJRdYtfmFxi7mi3dX`</summary>

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
  "parentUuid": "952460ab-c23f-475c-a072-5a6f9ad7aed3",
  "isSidechain": false,
  "requestId": "req_011CbFp6eV9fLrP3KuRYEdfS",
  "type": "assistant",
  "uuid": "1e844989-5a8b-4627-952a-43fcb417f110",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013BXfBDr37mv4ysXbeB8cKn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25484,
      "cache_read_input_tokens": 11846,
      "output_tokens": 364,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 364,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25484
          },
          "type": "message"
        }
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

_source line 14 · 2026-05-21T13:43:37.828Z_

<details><summary>↩ Tool result · `toolu_017SXrMWJRdYtfmFxi7mi3dX`</summary>

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
  "parentUuid": "1e844989-5a8b-4627-952a-43fcb417f110",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "2eb63f1b-7601-4640-8fa0-13de4f2c665d",
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
  "sourceToolAssistantUUID": "1e844989-5a8b-4627-952a-43fcb417f110",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 15 · 2026-05-21T13:43:38.723Z_

<details open><summary>🔧 Tool call — Glob · `toolu_015pWA1PnSb7CWUXVc3VGSA4`</summary>

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
  "parentUuid": "2eb63f1b-7601-4640-8fa0-13de4f2c665d",
  "isSidechain": false,
  "requestId": "req_011CbFp6eV9fLrP3KuRYEdfS",
  "type": "assistant",
  "uuid": "f2e8e94e-4554-4bf9-ad4b-89c051eeb308",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013BXfBDr37mv4ysXbeB8cKn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25484,
      "cache_read_input_tokens": 11846,
      "output_tokens": 364,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 364,
          "cache_read_input_tokens": 11846,
          "cache_creation_input_tokens": 25484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25484
          },
          "type": "message"
        }
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
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 15 warnin…",
  "leafUuid": "8fe17a6a-a200-45cc-97d9-f329afdf1951",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Assistant

_source line 18 · 2026-05-21T13:43:41.348Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read all the .tex files. Let me read them all in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8fe17a6a-a200-45cc-97d9-f329afdf1951",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "a50e3840-5a19-41e6-89eb-f575e7495283",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 19 · 2026-05-21T13:43:41.830Z_

读取所有 .tex 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a50e3840-5a19-41e6-89eb-f575e7495283",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "8560282c-e09f-4672-9628-d3b68f43effd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 20 · 2026-05-21T13:43:42.311Z_

<details open><summary>🔧 Tool call — Read · `toolu_01QyutPNcLTgpHWUPr21RT34`</summary>

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
  "parentUuid": "8560282c-e09f-4672-9628-d3b68f43effd",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "d90d056c-fb96-4b7a-8863-1ef0539ace3d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 21 · 2026-05-21T13:43:46.493Z_

<details><summary>↩ Tool result · `toolu_01LNCPABhqbFK5t8P9xsSHdm`</summary>

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
  "parentUuid": "dcb49032-00b2-483b-bdfd-d1a1fbaabbd1",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "78debc0a-5db1-4657-8e93-79396e16e8ac",
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
  "sourceToolAssistantUUID": "dcb49032-00b2-483b-bdfd-d1a1fbaabbd1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-21T13:43:42.316Z_

<details><summary>↩ Tool result · `toolu_01QyutPNcLTgpHWUPr21RT34`</summary>

```text
1	\begin{abstract}
2	LLM agent routing---deciding when to rely on internal reasoning versus external tool use---is typically addressed by training routers directly, without first understanding what mechanistic signal drives the routing preference. This absence of diagnostic methods risks building routers atop confounded or trivial signal. We propose an episode-level counterfactual framework that compares pure-strategy outcomes (internal-only vs.\ deterministic-only) to decompose routing signal into its mechanistic components before any router is constructed. Applying this framework to ScienceWorld (11 task types, 245 episodes), we find that 78.9\% of non-tie routing labels arise from death asymmetry---the internal strategy triggers catastrophic failure while the deterministic strategy survives. This finding is penalty-independent: a derived score-weighted measure, the Death Avoidance Factor, reaches 88--90\% across three model families (Qwen2.5-7B, Llama-3.1-8B, Gemma-2-9B), confirming convergence on a single dominant mechanism. Cross-environment probes on MATH and ALFWorld diagnose qualitatively different routing mechanisms---no extractable signal and information asymmetry, respectively---demonstrating the framework's generality. A ${\sim}$50-episode diagnostic pilot suffices to identify the dominant routing mechanism in a new environment, enabling informed build-vs-buy decisions before expensive router training.
3	\end{abstract}
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d90d056c-fb96-4b7a-8863-1ef0539ace3d",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "c2f32bc0-19f5-41f7-a7d5-86d42c07c941",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nLLM agent routing---deciding when to rely on internal reasoning versus external tool use---is typically addressed by training routers directly, without first understanding what mechanistic signal drives the routing preference. This absence of diagnostic methods risks building routers atop confounded or trivial signal. We propose an episode-level counterfactual framework that compares pure-strategy outcomes (internal-only vs.\\ deterministic-only) to decompose routing signal into its mechanistic components before any router is constructed. Applying this framework to ScienceWorld (11 task types, 245 episodes), we find that 78.9\\% of non-tie routing labels arise from death asymmetry---the internal strategy triggers catastrophic failure while the deterministic strategy survives. This finding is penalty-independent: a derived score-weighted measure, the Death Avoidance Factor, reaches 88--90\\% across three model families (Qwen2.5-7B, Llama-3.1-8B, Gemma-2-9B), confirming convergence on a single dominant mechanism. Cross-environment probes on MATH and ALFWorld diagnose qualitatively different routing mechanisms---no extractable signal and information asymmetry, respectively---demonstrating the framework's generality. A ${\\sim}$50-episode diagnostic pilot suffices to identify the dominant routing mechanism in a new environment, enabling informed build-vs-buy decisions before expensive router training.\n\\end{abstract}\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  },
  "sourceToolAssistantUUID": "d90d056c-fb96-4b7a-8863-1ef0539ace3d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-21T13:43:42.782Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UD3WxD9XbyJqUbz8RCwh12`</summary>

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
  "parentUuid": "c2f32bc0-19f5-41f7-a7d5-86d42c07c941",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "88505fc8-6c7d-450d-80cc-1020dcee24e5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-21T13:43:42.787Z_

<details><summary>↩ Tool result · `toolu_01UD3WxD9XbyJqUbz8RCwh12`</summary>

```text
1	\section{Introduction}
2	
3	Large language models deployed as interactive agents must repeatedly decide \emph{how} to compute: reason internally, or delegate to an external tool.
4	In ScienceWorld \citep{scienceworld-2022}, a text-based science simulation, internal reasoning is error-prone---the model may hallucinate state changes (e.g., that water has boiled when the stove was never activated)---while deterministic external computation eliminates such errors via exact state transitions. The practical question: \emph{when should an agent route computation externally versus internally?}
5	
6	Existing routing approaches frame this as a capability or efficiency decision: Toolformer \citep{toolformer-2023} inserts API calls by perplexity reduction; ART \citep{art-2023} decomposes tasks into tool-augmented programs; Chameleon \citep{chameleon-2023} selects heterogeneous modules per subtask; adaptive-computation methods route to different reasoning depths \citep{cogrouter-2026,ares-2026}, model tiers \citep{mtrouter-2026}, or episode-level model selection under sparse rewards \citep{budget-aware-routing-2026}; concurrent analyses further presuppose diverse routing signals~\citep{when2tool-2026,tool-use-tax-2026,to-call-or-not-2026}. The shared assumption---that routing signal stems from diverse sources and a learned router can exploit it---remains untested: no prior work has decomposed what drives routing decisions in interactive environments.
7	
8	We propose a \emph{diagnostic framework} comprising (i)~episode-level counterfactual labeling under pure strategies (\S\ref{sec:collection}--\ref{sec:labeling}), and (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\S\ref{sec:daf}). Applied to ScienceWorld, \textbf{78.9\% of non-tie routing labels arise from death asymmetry} (75 of 95), a penalty-independent finding. Under ScienceWorld's penalty ($P{=}100$), DAF reaches $90.4\%$ (95\% CI: $[81.1\%, 99.0\%]$). The internal strategy's hallucination-induced failures trigger catastrophic death ($-100$ penalty); once death episodes are removed, the gap collapses to $\Delta_{\text{nd}} = +2.84$ (\S\ref{sec:death-decomp}).
9	
10	This addresses a methodological gap: per-step oracle comparison degenerates under sparse rewards (97.4\% tie rate; \S\ref{sec:collection}), and keyword-based heuristics fail structurally (\S\ref{sec:baselines}). Our approach runs complete episodes under pure-internal (ReAct \citep{react-2023}) and pure-deterministic strategies, comparing episode outcomes.
11	
12	Cross-context checks probe specificity: MATH Level~4--5 ($N{=}795$, code interpreter) shows no routing signal without catastrophic failure ($73.5\%$ vs.\ $73.0\%$, $p = 0.81$); Llama-3.1-8B replication ($N{=}220$) confirms death dominance across model families (direction consistency 10/10; \S\ref{sec:cross-model}). Four intervention axes (retry, Reflexion~\citep{reflexion-2023}, $10{\times}$ scaling, action-space restriction) reduce death rates but none closes the gap to deterministic safety, with ${\geq}$12~pp residual gaps (\S\ref{sec:agent-improvement}).
13	An exploratory router (Qwen3 LoRA, 0.6B--4B) yields flat step-level balanced accuracy ($56$--$59\%$); at episode level, only 4B exceeds the always-deterministic baseline (\S\ref{sec:router-diagnostic}).
14	
15	Our contributions: (1)~an \textbf{episode-level counterfactual diagnostic framework} that overcomes per-step oracle degeneracy (97.4\% tie rate), decomposes routing signal via penalty-independent (label fraction) and penalty-dependent (DAF) metrics, and predicts routing value from a ${\sim}$50-episode pilot (validated 4/4 conditions; Appendix~\ref{app:decision-framework}); (2)~applying this framework to ScienceWorld, we find that \textbf{78.9\% of non-tie routing labels} stem from death asymmetry---a single mechanism that persists across four intervention axes and three model scales, contradicting the routing literature's implicit assumption of diverse signal sources (\S\ref{sec:death-decomp}--\ref{sec:agent-improvement}); (3)~\textbf{cross-model validation} (Llama-3.1-8B, DAF${=}88.2\%$; Gemma-2-9B-it, DAF${=}89.7\%$), four intervention axes, and cross-environment boundary probes (MATH, ALFWorld) confirm the framework's diagnostic utility and the robustness of the finding (\S\ref{sec:math-contrast}--\ref{sec:cross-model}).
16	
17	
18	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "88505fc8-6c7d-450d-80cc-1020dcee24e5",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "c5568664-5109-44ea-af97-157efea8d380",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\nLarge language models deployed as interactive agents must repeatedly decide \\emph{how} to compute: reason internally, or delegate to an external tool.\nIn ScienceWorld \\citep{scienceworld-2022}, a text-based science simulation, internal reasoning is error-prone---the model may hallucinate state changes (e.g., that water has boiled when the stove was never activated)---while deterministic external computation eliminates such errors via exact state transitions. The practical question: \\emph{when should an agent route computation externally versus internally?}\n\nExisting routing approaches frame this as a capability or efficiency decision: Toolformer \\citep{toolformer-2023} inserts API calls by perplexity reduction; ART \\citep{art-2023} decomposes tasks into tool-augmented programs; Chameleon \\citep{chameleon-2023} selects heterogeneous modules per subtask; adaptive-computation methods route to different reasoning depths \\citep{cogrouter-2026,ares-2026}, model tiers \\citep{mtrouter-2026}, or episode-level model selection under sparse rewards \\citep{budget-aware-routing-2026}; concurrent analyses further presuppose diverse routing signals~\\citep{when2tool-2026,tool-use-tax-2026,to-call-or-not-2026}. The shared assumption---that routing signal stems from diverse sources and a learned router can exploit it---remains untested: no prior work has decomposed what drives routing decisions in interactive environments.\n\nWe propose a \\emph{diagnostic framework} comprising (i)~episode-level counterfactual labeling under pure strategies (\\S\\ref{sec:collection}--\\ref{sec:labeling}), and (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\\S\\ref{sec:daf}). Applied to ScienceWorld, \\textbf{78.9\\% of non-tie routing labels arise from death asymmetry} (75 of 95), a penalty-independent finding. Under ScienceWorld's penalty ($P{=}100$), DAF reaches $90.4\\%$ (95\\% CI: $[81.1\\%, 99.0\\%]$). The internal strategy's hallucination-induced failures trigger catastrophic death ($-100$ penalty); once death episodes are removed, the gap collapses to $\\Delta_{\\text{nd}} = +2.84$ (\\S\\ref{sec:death-decomp}).\n\nThis addresses a methodological gap: per-step oracle comparison degenerates under sparse rewards (97.4\\% tie rate; \\S\\ref{sec:collection}), and keyword-based heuristics fail structurally (\\S\\ref{sec:baselines}). Our approach runs complete episodes under pure-internal (ReAct \\citep{react-2023}) and pure-deterministic strategies, comparing episode outcomes.\n\nCross-context checks probe specificity: MATH Level~4--5 ($N{=}795$, code interpreter) shows no routing signal without catastrophic failure ($73.5\\%$ vs.\\ $73.0\\%$, $p = 0.81$); Llama-3.1-8B replication ($N{=}220$) confirms death dominance across model families (direction consistency 10/10; \\S\\ref{sec:cross-model}). Four intervention axes (retry, Reflexion~\\citep{reflexion-2023}, $10{\\times}$ scaling, action-space restriction) reduce death rates but none closes the gap to deterministic safety, with ${\\geq}$12~pp residual gaps (\\S\\ref{sec:agent-improvement}).\nAn exploratory router (Qwen3 LoRA, 0.6B--4B) yields flat step-level balanced accuracy ($56$--$59\\%$); at episode level, only 4B exceeds the always-deterministic baseline (\\S\\ref{sec:router-diagnostic}).\n\nOur contributions: (1)~an \\textbf{episode-level counterfactual diagnostic framework} that overcomes per-step oracle degeneracy (97.4\\% tie rate), decomposes routing signal via penalty-independent (label fraction) and penalty-dependent (DAF) metrics, and predicts routing value from a ${\\sim}$50-episode pilot (validated 4/4 conditions; Appendix~\\ref{app:decision-framework}); (2)~applying this framework to ScienceWorld, we find that \\textbf{78.9\\% of non-tie routing labels} stem from death asymmetry---a single mechanism that persists across four intervention axes and three model scales, contradicting the routing literature's implicit assumption of diverse signal sources (\\S\\ref{sec:death-decomp}--\\ref{sec:agent-improvement}); (3)~\\textbf{cross-model validation} (Llama-3.1-8B, DAF${=}88.2\\%$; Gemma-2-9B-it, DAF${=}89.7\\%$), four intervention axes, and cross-environment boundary probes (MATH, ALFWorld) confirm the framework's diagnostic utility and the robustness of the finding (\\S\\ref{sec:math-contrast}--\\ref{sec:cross-model}).\n\n\n",
      "numLines": 18,
      "startLine": 1,
      "totalLines": 18
    }
  },
  "sourceToolAssistantUUID": "88505fc8-6c7d-450d-80cc-1020dcee24e5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-21T13:43:43.248Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UrNeZsgMPzgSuVByBhUTcc`</summary>

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
  "parentUuid": "c5568664-5109-44ea-af97-157efea8d380",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "aa265aca-5894-4cae-bcaf-ee65412a69c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 26 · 2026-05-21T13:43:43.254Z_

<details><summary>↩ Tool result · `toolu_01UrNeZsgMPzgSuVByBhUTcc`</summary>

```text
1	\section{Related Work}
2	
3	\paragraph{Tool Use and External Computation in LLMs.}
4	A growing body of work augments language models with external tools \citep{tool-learning-survey-2024}, spanning several functional categories.
5	\emph{Self-supervised} approaches learn tool invocation from loss signals: Toolformer \citep{toolformer-2023} inserts API calls filtered by perplexity reduction; ToolACE \citep{toolace-2025} curates synthetic data for function-calling accuracy.
6	\emph{Token-level} methods embed tools into the model vocabulary: ToolkenGPT \citep{toolkengpt-2023} represents tools as special tokens resolved at inference.
7	\emph{Task-level} decomposition routes subtasks to specialized modules: ART \citep{art-2023} generates tool-augmented programs; Chameleon \citep{chameleon-2023} composes heterogeneous modules per subtask.
8	\emph{RL-based} methods learn routing policies from reward: ReTool \citep{retool-2025} discovers when code execution is preferable to chain-of-thought.
9	All focus on \emph{learning to use tools}; we ask a prior question: \emph{what signal drives the routing decision?}
10	Concurrent work examines \emph{when} to invoke tools: tool-call decisions correlate with uncertainty~\citep{tool-overuse-illusion-2026}, are encoded in hidden states~\citep{when2tool-2026}, impose a ``tool-use tax''~\citep{tool-use-tax-2026}, or follow necessity-utility-affordability logic~\citep{to-call-or-not-2026}. Our decomposition yields a concrete answer: 78.9\% of non-tie routing labels trace to catastrophic-failure prevention.
11	
12	\paragraph{Adaptive Computation and Routing.}
13	Adaptive routing traces back to learned halting policies \citep{graves2016act}. In the LLM era, CogRouter \citep{cogrouter-2026} adapts reasoning depth per step, ARES \citep{ares-2026} selects among reasoning effort levels, Mixture-of-Recursions \citep{mixture-of-recursions-2025} learns token-level recursion depths, and MTRouter \citep{mtrouter-2026} addresses multi-turn routing.
14	RouteLLM \citep{routellm-2024} learns routers from preference data to select between strong and weak models.
15	\citet{budget-aware-routing-2026} train episode-level routing policies under sparse terminal rewards---the closest setting to ours; they optimize \emph{which} model to invoke, whereas we diagnose \emph{what} drives the routing decision.
16	
17	\paragraph{Counterfactual Evaluation in RL.}
18	Prior work generates counterfactual explanations by perturbing individual actions \citep{olson2021counterfactual, gajcin2023counterfactual, amitai2024explaining}; recent extensions target LLM agents~\citep{pona2025abstract,axis-2026,cso-2026}. We instead execute complete episodes under two strategies to decompose routing signal \emph{before} training.
19	
20	\paragraph{LLM Agent Environments and Reasoning.}
21	ScienceWorld \citep{scienceworld-2022} serves as our primary testbed; ALFWorld \citep{alfworld-2021} provides a complementary environment; AgentBench \citep{agentbench-2024} offers systematic evaluation. ReAct \citep{react-2023} serves as our internal baseline; Reflexion \citep{reflexion-2023} extends this with verbal self-reflection; LATS \citep{lats-2024} adds tree search. SALT~\citep{salt-2026} assigns step-level credit on ALFWorld, complementing our episode-level decomposition.
22	
23	\paragraph{Safe RL.}
24	Death avoidance connects to constrained MDPs \citep{altman1999constrained}, risk-sensitive RL \citep{mihatsch2002risk}, and classical safe RL \citep{garcia2015comprehensive,achiam2017cpo,moldovan2012safe}. Our routing achieves safety implicitly through computation mode selection. \citet{ruan2024failures} identify catastrophic actions as a distinct failure category; SafeRoute \citep{saferoute-2025} applies adaptive model selection for safety.
25	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "aa265aca-5894-4cae-bcaf-ee65412a69c1",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "94569846-5507-4d0b-b0cb-d4967898604e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\n\\paragraph{Tool Use and External Computation in LLMs.}\nA growing body of work augments language models with external tools \\citep{tool-learning-survey-2024}, spanning several functional categories.\n\\emph{Self-supervised} approaches learn tool invocation from loss signals: Toolformer \\citep{toolformer-2023} inserts API calls filtered by perplexity reduction; ToolACE \\citep{toolace-2025} curates synthetic data for function-calling accuracy.\n\\emph{Token-level} methods embed tools into the model vocabulary: ToolkenGPT \\citep{toolkengpt-2023} represents tools as special tokens resolved at inference.\n\\emph{Task-level} decomposition routes subtasks to specialized modules: ART \\citep{art-2023} generates tool-augmented programs; Chameleon \\citep{chameleon-2023} composes heterogeneous modules per subtask.\n\\emph{RL-based} methods learn routing policies from reward: ReTool \\citep{retool-2025} discovers when code execution is preferable to chain-of-thought.\nAll focus on \\emph{learning to use tools}; we ask a prior question: \\emph{what signal drives the routing decision?}\nConcurrent work examines \\emph{when} to invoke tools: tool-call decisions correlate with uncertainty~\\citep{tool-overuse-illusion-2026}, are encoded in hidden states~\\citep{when2tool-2026}, impose a ``tool-use tax''~\\citep{tool-use-tax-2026}, or follow necessity-utility-affordability logic~\\citep{to-call-or-not-2026}. Our decomposition yields a concrete answer: 78.9\\% of non-tie routing labels trace to catastrophic-failure prevention.\n\n\\paragraph{Adaptive Computation and Routing.}\nAdaptive routing traces back to learned halting policies \\citep{graves2016act}. In the LLM era, CogRouter \\citep{cogrouter-2026} adapts reasoning depth per step, ARES \\citep{ares-2026} selects among reasoning effort levels, Mixture-of-Recursions \\citep{mixture-of-recursions-2025} learns token-level recursion depths, and MTRouter \\citep{mtrouter-2026} addresses multi-turn routing.\nRouteLLM \\citep{routellm-2024} learns routers from preference data to select between strong and weak models.\n\\citet{budget-aware-routing-2026} train episode-level routing policies under sparse terminal rewards---the closest setting to ours; they optimize \\emph{which} model to invoke, whereas we diagnose \\emph{what} drives the routing decision.\n\n\\paragraph{Counterfactual Evaluation in RL.}\nPrior work generates counterfactual explanations by perturbing individual actions \\citep{olson2021counterfactual, gajcin2023counterfactual, amitai2024explaining}; recent extensions target LLM agents~\\citep{pona2025abstract,axis-2026,cso-2026}. We instead execute complete episodes under two strategies to decompose routing signal \\emph{before} training.\n\n\\paragraph{LLM Agent Environments and Reasoning.}\nScienceWorld \\citep{scienceworld-2022} serves as our primary testbed; ALFWorld \\citep{alfworld-2021} provides a complementary environment; AgentBench \\citep{agentbench-2024} offers systematic evaluation. ReAct \\citep{react-2023} serves as our internal baseline; Reflexion \\citep{reflexion-2023} extends this with verbal self-reflection; LATS \\citep{lats-2024} adds tree search. SALT~\\citep{salt-2026} assigns step-level credit on ALFWorld, complementing our episode-level decomposition.\n\n\\paragraph{Safe RL.}\nDeath avoidance connects to constrained MDPs \\citep{altman1999constrained}, risk-sensitive RL \\citep{mihatsch2002risk}, and classical safe RL \\citep{garcia2015comprehensive,achiam2017cpo,moldovan2012safe}. Our routing achieves safety implicitly through computation mode selection. \\citet{ruan2024failures} identify catastrophic actions as a distinct failure category; SafeRoute \\citep{saferoute-2025} applies adaptive model selection for safety.\n",
      "numLines": 25,
      "startLine": 1,
      "totalLines": 25
    }
  },
  "sourceToolAssistantUUID": "aa265aca-5894-4cae-bcaf-ee65412a69c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-21T13:43:43.682Z_

<details open><summary>🔧 Tool call — Read · `toolu_0148rWMbv8vBgRTe1DtcE47B`</summary>

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
  "parentUuid": "94569846-5507-4d0b-b0cb-d4967898604e",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "a594eb61-d201-48b3-8a85-80f99c5c3244",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 28 · 2026-05-21T13:43:43.688Z_

<details><summary>↩ Tool result · `toolu_0148rWMbv8vBgRTe1DtcE47B`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	Our diagnostic framework quantifies what drives routing signal in interactive environments through three components: (i)~episode-level counterfactual labeling that generates routing preferences from paired pure-strategy outcomes (\S\ref{sec:collection}--\ref{sec:labeling}); (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\S\ref{sec:daf}); and (iii)~the Signal Concentration Index (SCI), which measures whether routing signal is concentrated in a few task types or distributed systematically (Appendix~\ref{app:sci}). Episode-level bootstrap resampling provides 95\% confidence intervals for all metrics.
5	
6	\subsection{Problem Setup}
7	\label{sec:problem-setup}
8	
9	Consider an interactive environment with observation space $\mathcal{O}$ and action space $\mathcal{A}$. An agent policy $\pi: \mathcal{O}^* \rightarrow \mathcal{A}$ maps observation histories to actions. We define two computation modes $\mathcal{M} = \{{\tt int}, {\tt det}\}$: \textbf{internal} (${\tt int}$), where the agent predicts intermediate observations via chain-of-thought reasoning (ReAct~\citep{react-2023}), with prediction errors compounding across steps; and \textbf{deterministic}\footnote{The term ``deterministic'' denotes different information advantages across environments: in ScienceWorld, an oracle simulator providing ground-truth action outcomes; in MATH, a code interpreter verifying computations; in ALFWorld, admissible-action enumeration eliminating hallucination risk. These qualitative differences affect what routing signals the framework can detect.} (${\tt det}$), where the agent receives ground-truth observations from the environment simulator at each step. A \emph{routing policy} $\rho: \mathcal{O}^* \rightarrow \mathcal{M}$ selects which computation mode to use at each step; our analysis investigates what signal is available to learn $\rho$.
10	
11	\subsection{Counterfactual Episode Collection}
12	\label{sec:collection}
13	
14	Per-step oracle labeling assigns routing labels by comparing single-step outcomes under each computation mode. Under sparse terminal rewards, this approach degenerates: on ScienceWorld \citep{scienceworld-2022}, 97.4\% of steps produce identical intermediate scores regardless of computation mode (5{,}935 of 6{,}094 steps across 11 prescreened task types), yielding no per-step routing signal. The 97.4\% tie rate arises because ScienceWorld assigns rewards only at episode termination; intermediate steps update environment state but do not change the score, so a per-step oracle can only distinguish strategies through downstream consequences visible at episode end. Episode-level comparison is therefore the principled granularity for sparse-reward environments, not a fallback from per-step analysis: it directly measures whether one strategy produces better terminal outcomes than the other, bypassing the uninformative intermediate steps entirely.
15	
16	\paragraph{Pure-strategy trajectories.}
17	For a task instance $t$ and computation mode $m \in \mathcal{M}$, a \emph{pure-strategy trajectory} is the complete episode obtained by applying mode $m$ at every step:
18	\begin{equation}
19	    \tau_m^{(t)} = (o_1, a_1, o_2, a_2, \ldots, o_T, a_T)
20	\end{equation}
21	where $T \leq T_{\max}$ is the episode length (capped at $T_{\max} = 30$ steps). Both trajectories $\tau_{\tt int}^{(t)}$ and $\tau_{\tt det}^{(t)}$ are executed under identical initial conditions (same random seed, same task variation), so performance differences arise solely from the computation mode choice.
22	
23	Each trajectory $\tau$ yields a terminal score $s(\tau) \in \mathbb{Z}$ and a death indicator $d(\tau) \in \{0, 1\}$. When the agent dies ($d = 1$), the environment imposes a penalty: $s(\tau) = -P$ where $P > 0$ ($P = 100$ in ScienceWorld). The episode pair produces a tuple:
24	\begin{multline}
25	    \bigl(s^{\tt int}, s^{\tt det}, d^{\tt int}, d^{\tt det}\bigr) \triangleq \\
26	    \bigl(s(\tau_{\tt int}),\, s(\tau_{\tt det}),\, d(\tau_{\tt int}),\, d(\tau_{\tt det})\bigr)
27	\end{multline}
28	
29	We use Qwen2.5-7B-Instruct~\citep{qwen25-2024} (vLLM) on ScienceWorld \citep{scienceworld-2022}, a text-based environment spanning 30 task types with a $-100$ death penalty. After prescreening, we collect 245 episode pairs across 11 task types (20--40 per type). The framework is applicable to any environment where paired episodes under two computation modes can be collected with binary success/failure indicators. We apply it unchanged to ALFWorld and MATH in \S\ref{sec:math-contrast}--\ref{sec:cross-env}.
30	
31	\subsection{Episode-Level Labeling}
32	\label{sec:labeling}
33	
34	We define a labeling function $L$ that maps a counterfactual pair to a routing preference:
35	\begin{multline}
36	    L\!\bigl(\tau_{\tt int}^{(t)}, \tau_{\tt det}^{(t)}\bigr) \;\rightarrow \\
37	    \ell \in \{{\tt det\text{-}pref},\; {\tt int\text{-}pref},\; {\tt no\text{-}pref}\}
38	\end{multline}
39	
40	The labeling function is \emph{death-aware}: it prioritizes survival over score, then compares scores among same-status episodes (Algorithm~\ref{alg:labeling}; Appendix~\ref{app:labeling}). ScienceWorld scores are integer-valued, so we use exact (in)equality with no threshold. Figure~\ref{fig:pipeline} illustrates the overall pipeline; label distributions are reported in \S\ref{sec:death-decomp}.
41	
42	\begin{figure}[t]
43	\centering
44	\includegraphics[width=\columnwidth]{figures/pipeline_overview.pdf}
45	\caption{Counterfactual episode collection and analysis pipeline. Each task instance is run under both pure strategies independently, producing episode-level labels via Algorithm~\ref{alg:labeling}.}
46	\label{fig:pipeline}
47	\end{figure}
48	
49	\subsection{Death Avoidance Factor}
50	\label{sec:daf}
51	
52	To quantify the contribution of death avoidance to routing signal, we decompose the mean score gap between strategies. Let $\delta = \mathbb{E}[d^{\tt int}] - \mathbb{E}[d^{\tt det}]$ denote the death-rate differential and $\Delta_{\text{nd}}$ the mean score gap restricted to episodes where neither strategy dies. Partitioning episodes by death status, death-asymmetric episodes (where only one strategy dies) contribute a per-episode gap of $P + \bar{s}_{\text{surv}}$, where $\bar{s}_{\text{surv}}$ is the surviving strategy's mean score; when $\bar{s}_{\text{surv}} \ll P$ (in our data, $\bar{s}_{\text{surv}} = 0.87$, or $0.9\%$ of $P$), these episodes contribute ${\approx}\,\delta P$ in aggregate. The full gap thus decomposes as:
53	\begin{equation}
54	    \Delta_{\text{full}} \approx \underbrace{\delta \cdot P}_{\text{death contribution}} + \Delta_{\text{nd}}
55	\end{equation}
56	The approximation residual is $29.60 - 29.37 = 0.23$ ($0.8\%$ of $\Delta_{\text{full}}$).
57	
58	We define the Death Avoidance Factor (DAF) as the fraction of the full score gap attributable to death avoidance:
59	\begin{equation}
60	    \text{DAF} = 1 - \frac{\Delta_{\text{nd}}}{\Delta_{\text{full}}} \approx \frac{\delta P}{\delta P + \Delta_{\text{nd}}}
61	\end{equation}%
62	\footnote{When $\Delta_{\text{nd}} < 0$ (deterministic strategy scores lower than internal on non-death episodes), DAF exceeds 1; death avoidance then overcompensates for a non-death disadvantage.}
63	
64	Since DAF $= \delta P / (\delta P + \Delta_{\text{nd}})$, it increases monotonically with $P$, a mathematical consequence rather than an empirical finding. We therefore report both DAF at the environment default ($P{=}100$) and the penalty-independent death-asymmetry label fraction as complementary metrics. In ScienceWorld, $P$ affects only post-hoc score calculation; the agent's policy (ReAct prompting) does not include $P$ in its observation, so death rates and $\Delta_{\text{nd}}$ are $P$-invariant by design~\citep{ng1999policy} (Appendix~\ref{app:penalty}).
65	
66	\paragraph{Relationship between DAF and label fraction.}
67	DAF (90.4\%) exceeds the label fraction (78.9\%) because death episodes carry disproportionately large score gaps ($P{=}100 \gg$ typical non-death $\Delta{\approx}29$), amplifying their weight in score-weighted aggregation. The label fraction---invariant to penalty magnitude---serves as the primary finding; DAF reflects the score-space reality under ScienceWorld's reward structure.
68	
69	\paragraph{Statistical inference.}
70	We quantify uncertainty via episode-level bootstrap resampling ($B = 10{,}000$). Each resample draws $N = 245$ episodes with replacement, recomputes all metrics, and derives percentile-based 95\% CIs. We resample at the episode level (not the step level) because the episode is the unit of counterfactual comparison. Penalty sensitivity analysis across hypothetical $P$ values is in Appendix~\ref{app:penalty}.
71	
72	We also measure whether death-avoidance signal is concentrated in a few task types via a Signal Concentration Index (SCI $\in [0, 1]$; Appendix~\ref{app:sci}), reported in \S\ref{sec:death-decomp}.
73	
74	\paragraph{Scope of episode-level analysis.}
75	At step level, 97.4\% of oracle comparisons yield ties (\S\ref{sec:collection}); of 2{,}040 training steps, only 0.3\% exhibit strict directional conflict with episode labels, with 60.3\% pre-event neutral (neither strategy advantaged). Episode labels thus apply correct direction to uninformative steps---a granularity mismatch, not label error---explaining why step-level router training approaches chance performance (\S\ref{sec:router-diagnostic}).
76	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a594eb61-d201-48b3-8a85-80f99c5c3244",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "23548f2d-1bd4-496b-b89a-31b37c2c7a91",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\nOur diagnostic framework quantifies what drives routing signal in interactive environments through three components: (i)~episode-level counterfactual labeling that generates routing preferences from paired pure-strategy outcomes (\\S\\ref{sec:collection}--\\ref{sec:labeling}); (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\\S\\ref{sec:daf}); and (iii)~the Signal Concentration Index (SCI), which measures whether routing signal is concentrated in a few task types or distributed systematically (Appendix~\\ref{app:sci}). Episode-level bootstrap resampling provides 95\\% confidence intervals for all metrics.\n\n\\subsection{Problem Setup}\n\\label{sec:problem-setup}\n\nConsider an interactive environment with observation space $\\mathcal{O}$ and action space $\\mathcal{A}$. An agent policy $\\pi: \\mathcal{O}^* \\rightarrow \\mathcal{A}$ maps observation histories to actions. We define two computation modes $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$: \\textbf{internal} (${\\tt int}$), where the agent predicts intermediate observations via chain-of-thought reasoning (ReAct~\\citep{react-2023}), with prediction errors compounding across steps; and \\textbf{deterministic}\\footnote{The term ``deterministic'' denotes different information advantages across environments: in ScienceWorld, an oracle simulator providing ground-truth action outcomes; in MATH, a code interpreter verifying computations; in ALFWorld, admissible-action enumeration eliminating hallucination risk. These qualitative differences affect what routing signals the framework can detect.} (${\\tt det}$), where the agent receives ground-truth observations from the environment simulator at each step. A \\emph{routing policy} $\\rho: \\mathcal{O}^* \\rightarrow \\mathcal{M}$ selects which computation mode to use at each step; our analysis investigates what signal is available to learn $\\rho$.\n\n\\subsection{Counterfactual Episode Collection}\n\\label{sec:collection}\n\nPer-step oracle labeling assigns routing labels by comparing single-step outcomes under each computation mode. Under sparse terminal rewards, this approach degenerates: on ScienceWorld \\citep{scienceworld-2022}, 97.4\\% of steps produce identical intermediate scores regardless of computation mode (5{,}935 of 6{,}094 steps across 11 prescreened task types), yielding no per-step routing signal. The 97.4\\% tie rate arises because ScienceWorld assigns rewards only at episode termination; intermediate steps update environment state but do not change the score, so a per-step oracle can only distinguish strategies through downstream consequences visible at episode end. Episode-level comparison is therefore the principled granularity for sparse-reward environments, not a fallback from per-step analysis: it directly measures whether one strategy produces better terminal outcomes than the other, bypassing the uninformative intermediate steps entirely.\n\n\\paragraph{Pure-strategy trajectories.}\nFor a task instance $t$ and computation mode $m \\in \\mathcal{M}$, a \\emph{pure-strategy trajectory} is the complete episode obtained by applying mode $m$ at every step:\n\\begin{equation}\n    \\tau_m^{(t)} = (o_1, a_1, o_2, a_2, \\ldots, o_T, a_T)\n\\end{equation}\nwhere $T \\leq T_{\\max}$ is the episode length (capped at $T_{\\max} = 30$ steps). Both trajectories $\\tau_{\\tt int}^{(t)}$ and $\\tau_{\\tt det}^{(t)}$ are executed under identical initial conditions (same random seed, same task variation), so performance differences arise solely from the computation mode choice.\n\nEach trajectory $\\tau$ yields a terminal score $s(\\tau) \\in \\mathbb{Z}$ and a death indicator $d(\\tau) \\in \\{0, 1\\}$. When the agent dies ($d = 1$), the environment imposes a penalty: $s(\\tau) = -P$ where $P > 0$ ($P = 100$ in ScienceWorld). The episode pair produces a tuple:\n\\begin{multline}\n    \\bigl(s^{\\tt int}, s^{\\tt det}, d^{\\tt int}, d^{\\tt det}\\bigr) \\triangleq \\\\\n    \\bigl(s(\\tau_{\\tt int}),\\, s(\\tau_{\\tt det}),\\, d(\\tau_{\\tt int}),\\, d(\\tau_{\\tt det})\\bigr)\n\\end{multline}\n\nWe use Qwen2.5-7B-Instruct~\\citep{qwen25-2024} (vLLM) on ScienceWorld \\citep{scienceworld-2022}, a text-based environment spanning 30 task types with a $-100$ death penalty. After prescreening, we collect 245 episode pairs across 11 task types (20--40 per type). The framework is applicable to any environment where paired episodes under two computation modes can be collected with binary success/failure indicators. We apply it unchanged to ALFWorld and MATH in \\S\\ref{sec:math-contrast}--\\ref{sec:cross-env}.\n\n\\subsection{Episode-Level Labeling}\n\\label{sec:labeling}\n\nWe define a labeling function $L$ that maps a counterfactual pair to a routing preference:\n\\begin{multline}\n    L\\!\\bigl(\\tau_{\\tt int}^{(t)}, \\tau_{\\tt det}^{(t)}\\bigr) \\;\\rightarrow \\\\\n    \\ell \\in \\{{\\tt det\\text{-}pref},\\; {\\tt int\\text{-}pref},\\; {\\tt no\\text{-}pref}\\}\n\\end{multline}\n\nThe labeling function is \\emph{death-aware}: it prioritizes survival over score, then compares scores among same-status episodes (Algorithm~\\ref{alg:labeling}; Appendix~\\ref{app:labeling}). ScienceWorld scores are integer-valued, so we use exact (in)equality with no threshold. Figure~\\ref{fig:pipeline} illustrates the overall pipeline; label distributions are reported in \\S\\ref{sec:death-decomp}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/pipeline_overview.pdf}\n\\caption{Counterfactual episode collection and analysis pipeline. Each task instance is run under both pure strategies independently, producing episode-level labels via Algorithm~\\ref{alg:labeling}.}\n\\label{fig:pipeline}\n\\end{figure}\n\n\\subsection{Death Avoidance Factor}\n\\label{sec:daf}\n\nTo quantify the contribution of death avoidance to routing signal, we decompose the mean score gap between strategies. Let $\\delta = \\mathbb{E}[d^{\\tt int}] - \\mathbb{E}[d^{\\tt det}]$ denote the death-rate differential and $\\Delta_{\\text{nd}}$ the mean score gap restricted to episodes where neither strategy dies. Partitioning episodes by death status, death-asymmetric episodes (where only one strategy dies) contribute a per-episode gap of $P + \\bar{s}_{\\text{surv}}$, where $\\bar{s}_{\\text{surv}}$ is the surviving strategy's mean score; when $\\bar{s}_{\\text{surv}} \\ll P$ (in our data, $\\bar{s}_{\\text{surv}} = 0.87$, or $0.9\\%$ of $P$), these episodes contribute ${\\approx}\\,\\delta P$ in aggregate. The full gap thus decomposes as:\n\\begin{equation}\n    \\Delta_{\\text{full}} \\approx \\underbrace{\\delta \\cdot P}_{\\text{death contribution}} + \\Delta_{\\text{nd}}\n\\end{equation}\nThe approximation residual is $29.60 - 29.37 = 0.23$ ($0.8\\%$ of $\\Delta_{\\text{full}}$).\n\nWe define the Death Avoidance Factor (DAF) as the fraction of the full score gap attributable to death avoidance:\n\\begin{equation}\n    \\text{DAF} = 1 - \\frac{\\Delta_{\\text{nd}}}{\\Delta_{\\text{full}}} \\approx \\frac{\\delta P}{\\delta P + \\Delta_{\\text{nd}}}\n\\end{equation}%\n\\footnote{When $\\Delta_{\\text{nd}} < 0$ (deterministic strategy scores lower than internal on non-death episodes), DAF exceeds 1; death avoidance then overcompensates for a non-death disadvantage.}\n\nSince DAF $= \\delta P / (\\delta P + \\Delta_{\\text{nd}})$, it increases monotonically with $P$, a mathematical consequence rather than an empirical finding. We therefore report both DAF at the environment default ($P{=}100$) and the penalty-independent death-asymmetry label fraction as complementary metrics. In ScienceWorld, $P$ affects only post-hoc score calculation; the agent's policy (ReAct prompting) does not include $P$ in its observation, so death rates and $\\Delta_{\\text{nd}}$ are $P$-invariant by design~\\citep{ng1999policy} (Appendix~\\ref{app:penalty}).\n\n\\paragraph{Relationship between DAF and label fraction.}\nDAF (90.4\\%) exceeds the label fraction (78.9\\%) because death episodes carry disproportionately large score gaps ($P{=}100 \\gg$ typical non-death $\\Delta{\\approx}29$), amplifying their weight in score-weighted aggregation. The label fraction---invariant to penalty magnitude---serves as the primary finding; DAF reflects the score-space reality under ScienceWorld's reward structure.\n\n\\paragraph{Statistical inference.}\nWe quantify uncertainty via episode-level bootstrap resampling ($B = 10{,}000$). Each resample draws $N = 245$ episodes with replacement, recomputes all metrics, and derives percentile-based 95\\% CIs. We resample at the episode level (not the step level) because the episode is the unit of counterfactual comparison. Penalty sensitivity analysis across hypothetical $P$ values is in Appendix~\\ref{app:penalty}.\n\nWe also measure whether death-avoidance signal is concentrated in a few task types via a Signal Concentration Index (SCI $\\in [0, 1]$; Appendix~\\ref{app:sci}), reported in \\S\\ref{sec:death-decomp}.\n\n\\paragraph{Scope of episode-level analysis.}\nAt step level, 97.4\\% of oracle comparisons yield ties (\\S\\ref{sec:collection}); of 2{,}040 training steps, only 0.3\\% exhibit strict directional conflict with episode labels, with 60.3\\% pre-event neutral (neither strategy advantaged). Episode labels thus apply correct direction to uninformative steps---a granularity mismatch, not label error---explaining why step-level router training approaches chance performance (\\S\\ref{sec:router-diagnostic}).\n",
      "numLines": 76,
      "startLine": 1,
      "totalLines": 76
    }
  },
  "sourceToolAssistantUUID": "a594eb61-d201-48b3-8a85-80f99c5c3244",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-21T13:43:44.671Z_

<details open><summary>🔧 Tool call — Read · `toolu_013Fn4jqFZs6WDuauF72iKqS`</summary>

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
  "parentUuid": "23548f2d-1bd4-496b-b89a-31b37c2c7a91",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "87990f20-261b-47b3-a3b4-2d5952c1dd71",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 30 · 2026-05-21T13:43:44.676Z_

<details><summary>↩ Tool result · `toolu_013Fn4jqFZs6WDuauF72iKqS`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We analyze 11 of ScienceWorld's 30 task types (245 episodes); the 19 excluded types (63\%) lack actionable routing signal due to development contamination (5), taxonomic redundancy (7), or agent-floor performance (7). This scope limits generalizability: conclusions apply to the included subset, not to all ScienceWorld tasks. An anti-cherry-picking analysis confirms that death dominance holds in 18 of these 19 types, with a mean $\Delta\text{DR} = +38.2$\,pp exceeding the included tasks' $+28.7$\,pp (Appendix~\ref{app:per-task}). Extended validation at $n{=}20$ on five representative excluded tasks confirms this direction ($\overline{\Delta\text{DR}} = +32.0$\,pp; Appendix~\ref{app:extended-validation}). A reasoning-depth ablation ($n{=}120$) found no significant difference between internal strategy variants ($p > 0.26$; Appendix~\ref{app:ablations}).
5	
6	\subsection{Death Avoidance Decomposition}
7	\label{sec:death-decomp}
8	
9	\begin{figure}[t]
10	\centering
11	\includegraphics[width=0.85\columnwidth]{figures/fig1_daf_scatter.pdf}
12	\caption{Per-task scatter: death rate differential (internal $-$ deterministic) vs.\ performance gap ($\Delta_{\text{full}}$). $r = 0.97$ (Spearman's $\rho = 0.986$; Appendix~\ref{app:per-task}), $p < 10^{-6}$, $n = 11$ task types. Since $\Delta_{\text{full}} \approx \delta P + \Delta_{\text{nd}}$ with $P$ constant, $r \to 1$ as DAF $\to 1$; the near-perfect correlation is a structural consequence of death dominance, not an independent finding (\S\ref{sec:death-decomp}).}
13	\label{fig:decomposition}
14	\end{figure}
15	
16	Of the 95 non-tie routing labels, 75 (78.9\%) arise from death asymmetry: the internal strategy triggers a catastrophic $-100$ penalty while the deterministic strategy survives. This penalty-independent label fraction is the primary diagnostic metric. Of these 75, 54 are sole-signal labels (both strategies score zero without death, so death avoidance was the \emph{sole} discriminating signal). At $P{=}0$, the 54 sole-signal labels reduce to ties, leaving 41 non-tie labels of which 21 (51.2\%) still involve death asymmetry; the labeling function itself is penalty-independent (Algorithm~\ref{alg:labeling}), but the practical routing value of death avoidance requires $P > 0$.
17	
18	Of 245 episodes, 150 (61.2\%) are ties---neither strategy outperforms the other---indicating that routing is relevant in only 38.8\% of episodes. Among these, death avoidance dominates. The Death Avoidance Factor, a derived penalty-dependent measure, quantifies death's contribution to the total performance gap: DAF $= 90.4\%$ at $P{=}100$ ($\Delta_{\text{full}} = +29.60$, $\Delta_{\text{nd}} = +2.84$; 95\% CI: $[81.1\%, 99.0\%]$, episode-level bootstrap, $B{=}10{,}000$). DAF varies with penalty magnitude ($50.4\%$ at $P{=}10$; $82.6\%$ at $P{=}50$; Appendix~\ref{app:penalty}), confirming that the 78.9\% label fraction provides the more robust characterization. When $\Delta_{\text{nd}} \to 0$, DAF $\to 1$ is algebraic necessity regardless of actual death dominance; conversely, when $\Delta_{\text{nd}} < 0$ (as in Reflexion $N{\geq}3$; \S\ref{sec:agent-improvement}), DAF exceeds 100\%, reflecting that death asymmetry more than accounts for the full gap.
19	
20	\paragraph{Per-task correlation structure.}
21	The internal strategy dies in 42.9\% of episodes versus 16.3\% for deterministic (2.6$\times$), consistent with the internal strategy's reliance on self-generated observations that compound prediction errors across steps. Per-task, death rate differential correlates with $\Delta_{\text{full}}$ ($r = 0.97$, $p < 10^{-6}$; Figure~\ref{fig:decomposition}; Appendix~\ref{app:correlation}). Since $P$ is constant across all task types, $\Delta_{\text{full}} = P \cdot \delta + \Delta_{\text{nd}}$ makes $\Delta_{\text{full}}$ a linear function of $\delta$ with residual $\Delta_{\text{nd}}$; when DAF $\rightarrow 1$, this residual vanishes and $r \rightarrow 1$ by construction. The near-perfect correlation is therefore a mathematical consequence of death dominance, not an independent empirical finding. We retain it as an internal consistency check. The correlation drops below significance at $P \leq 25$ (Appendix~\ref{app:penalty}). Of 245 episodes, 86 are \texttt{det\_preferred}, 9 \texttt{internal\_preferred}, and 150 \texttt{no\_preference}.
22	
23	\paragraph{Signal concentration and binary structure.}
24	The Signal Concentration Index (SCI $= 0.2147$; Appendix~\ref{app:sci}) confirms low concentration: the top-3 task types account for only $39.8\%$ of total death-rate differential. The aggregate 78.9\% reflects a per-task binary structure: all 10 death-prone task types produce 100\% death-asymmetry labels, while \texttt{find-non-living-thing} (zero deaths, $\Delta = +9.58$ from non-death scores) produces 0\%. The framework thus diagnoses a binary property (``is this environment death-dominated?'') rather than a continuous routing signal. Removing \texttt{find-non-living-thing} raises the label fraction to 100\% and yields DAF $\geq$100\% ($\Delta_\text{nd} \leq 0$; death avoidance fully accounts for the routing gap among remaining task types; Appendix~\ref{app:loto-daf}).
25	
26	\paragraph{Sensitivity and seed robustness.}
27	Non-clustered episode-level bootstrap ($B = 10{,}000$) yields 95\% CI $[81.1\%, 99.0\%]$ for DAF, independent of cluster assumptions, with Cohen's $d = 3.02$ (interpret cautiously given $K{=}11$ task types). Leave-one-task-out analysis confirms stability (label fraction range: 75.9\%--78.9\%; Appendix~\ref{app:loto-daf}); an independent seed replication ($N{=}220$) yields DAF $= 89.7\%$, within 0.7~pp (Appendix~\ref{app:seed-robustness}). As a conservative check, wild cluster bootstrap treating each task type as a cluster yields $p = 0.002$; however, with $K{=}11$ clusters this test falls below the $K{\geq}20$--$40$ threshold recommended for reliable inference~\citep{cameron-2008,webb-2023}, so we rely on the non-clustered bootstrap as primary. All 28 death-prone tasks share the same direction (Appendices~\ref{app:wild-cluster}--\ref{app:per-task-ci}).
28	
29	\subsection{Multi-Model Validation}
30	\label{sec:cross-model}
31	
32	A Llama-3.1-8B-Instruct~\citep{llama3-2024} cross-model replication across all 11 task types ($N{=}220$) confirms that death dominance replicates across model families: internal death rate $41.4\%$ vs.\ deterministic $11.4\%$ (death-rate differential $+30.0$~pp), DAF $= 88.2\%$ (95\% CI: $[80.2\%, 95.1\%]$; $\Delta_{\text{full}} = +33.17$, $\Delta_{\text{nd}} = +3.9$), with direction consistency 10/10 on death-prone tasks, 83 deterministic-preferred, 3 internal-preferred (1.4\%, all death-asymmetry reversals), and 134 no-preference labels.
33	Both models exhibit nearly identical internal vulnerability (${\sim}$42\%: Qwen $42.9\%$, Llama $41.4\%$), confirming that death-prone failure is empirically dominated; the differential magnitude varies ($+26.5$~pp Qwen, $+30.0$~pp Llama) because deterministic strategy safety is model-dependent ($16.3\%$ vs.\ $11.4\%$).
34	\texttt{identify-life-stages-1} shows cross-model precision matching ($55\%$/$10\%$/$+45$~pp in both models).
35	\texttt{find-non-living-thing} shows zero deaths in both models, consistent with its majority-class answer distribution (Appendix~\ref{app:per-task}). Cross-model routing transfer is vacuously correct: Llama produces zero internal-preferred episodes, so Qwen-derived routing rules (always-deterministic) trivially match, confirming that routing signal is environment-determined rather than model-specific.
36	A third model family, Gemma-2-9B-it~\citep{gemma2-2024} (sliding window attention, vs.\ full attention in Qwen/Llama), independently confirms the pattern: DAF${=}89.7\%$ (95\% CI $[79.5\%, 98.4\%]$; $N{=}220$), with all 10 death-prone task types showing positive $\Delta$DR (Appendix~\ref{app:cross-model}). Three architecturally distinct models thus converge on DAF $88$--$90\%$ (spread 2.2~pp); $10{\times}$ scaling to 72B (\S\ref{sec:agent-improvement}) confirms persistence across capability levels.
37	
38	\subsection{Agent Improvement Baselines}
39	\label{sec:agent-improvement}
40	
41	\begin{table}[t]
42	\centering
43	\small
44	\begin{tabular}{@{}lrr@{}}
45	\toprule
46	Condition & Death\% & $N$ \\
47	\midrule
48	Single-trial baseline & 42.9 & 245 \\
49	Reflexion ($3{\times}$) & 31.4 & 220 \\
50	Qwen2.5-72B ($10{\times}$) & 30.6 & 255 \\
51	Deterministic baseline & 16.3 & 245 \\
52	\midrule
53	\multicolumn{3}{@{}l}{\textit{10 death-prone tasks only:}} \\
54	Death-prone baseline & 48.0 & 200 \\
55	Retry ($5{\times}$) & 43.5 & 200 \\
56	\bottomrule
57	\end{tabular}
58	\caption{Internal-strategy death rates under agent improvement methods. Top: all 11 tasks (72B: independently collected at both internal and deterministic). Bottom: 10 death-prone tasks (\texttt{find-non-living-thing} excluded, 0\% death at all scales). All interventions reduce death rate but none approaches deterministic-level safety.}
59	\label{tab:agent-improvement}
60	\end{table}
61	
62	We test whether agent-level improvement reduces death dominance (Table~\ref{tab:agent-improvement}). Retry ($N{=}5$ attempts without self-correction) yields marginal reduction on death-prone tasks ($43.5\%$ vs.\ $48.0\%$ baseline, $\Delta = -4.5$~pp). Reflexion~\citep{reflexion-2023} (verbal self-reflection between trials) reduces death to 31.4\% across all 11 tasks by rescuing 29.3\% of first-trial deaths, but the gap to deterministic remains 15.1~pp; on the 10 death-prone tasks, Reflexion achieves ${\sim}$35\%. Under Reflexion ($N{=}3$, matched-episode analysis), $\Delta_{\text{nd}} = -0.47$, yielding DAF $> 100\%$: the deterministic advantage is entirely attributable to death avoidance, and in non-death episodes the self-correcting agent slightly outperforms the deterministic baseline. Scaling to Qwen2.5-72B ($10{\times}$ parameters; both internal and deterministic strategies independently collected at 72B, 255 episodes across all 11 task types) reduces death rate to $30.6\%$. The 72B deterministic strategy achieves $2.75\%$ death rate ($\Delta\text{DR} = +27.8$~pp), and $\Delta_{\text{nd}} = +2.28$, yielding DAF $= 92.4\%$ (7B: $90.4\%$); scaling lowers death rate but leaves death dominance intact.
63	
64	\paragraph{Dose-response analysis.}
65	We extend both interventions to $N{=}5$ trials on death-prone tasks ($n{=}200$; Figure~\ref{fig:dose-response}). Retry is nearly flat ($48.0\% \to 43.5\%$, $\Delta = -4.5$~pp over five trials). Reflexion drops steeply to $34.0\%$ at $N{=}3$ ($\Delta = -13.5$~pp, $z = 2.75$, $p = 0.003$) then stabilizes ($34$--$36.5\%$ for $N \geq 3$, pairwise $p > 0.5$). With $n{=}200$ paired episodes, the minimum detectable effect is ${\sim}8$~pp ($\alpha = 0.05$, 80\% power): the key $N{=}1{\to}3$ decline is well-powered; the stabilization claim ($N{=}3{\to}5$, $+1.0$~pp) is also supported, since a ${\geq}8$~pp improvement would be detected. We characterize this as suggestive evidence of a Reflexion ceiling rather than a conclusive demonstration. Retry's per-trial conditional death rate stays constant at ${\sim}48\%$; Reflexion's declines to ${\sim}31\%$ by Trial~3 (per-task breakdown in Appendix~\ref{app:dose-response}).
66	
67	\begin{figure}[t]
68	\centering
69	\includegraphics[width=\columnwidth]{figures/dose_response.pdf}
70	\caption{Death rate as a function of trial count ($N$) for Retry and Reflexion on 10 death-prone tasks ($n{=}200$). Retry (blue) is nearly flat; Reflexion (red) drops steeply through $N{=}3$ then shows no statistically detectable improvement beyond $N{=}3$ (Wilson CIs for $N{=}3,4,5$ overlap substantially). Horizontal lines: 72B scaling baseline ($30.6\%$, all 11 tasks) and deterministic baseline ($16.3\%$). Error bands: Wilson 95\% CIs.}
71	\label{fig:dose-response}
72	\end{figure}
73	
74	\subsection{Cross-Environment Boundary Probes}
75	\label{sec:math-contrast}
76	\label{sec:cross-env}
77	
78	We examine MATH and ALFWorld as boundary probes---not cross-domain validation---testing framework applicability across environments that instantiate ``deterministic computation'' differently (oracle simulator, code interpreter, admissible-action enumeration; see operationalization in \S\ref{sec:problem-setup}).
79	
80	\paragraph{MATH.} On MATH Level~4--5~\citep{math-2021} ($N{=}795$, code interpreter), internal reasoning and code interpretation achieve near-identical accuracy ($73.5\%$ vs.\ $73.0\%$, McNemar $p = 0.81$), with 84.4\% no-preference. Without catastrophic failure, no routing signal emerges.
81	
82	\paragraph{ALFWorld.} ALFWorld~\citep{alfworld-2021} (6 task types, 135 games) provides the deterministic strategy with admissible actions---an information asymmetry rather than a computation mode switch, with no death mechanism ($\delta = 0$, DAF $= 0\%$). With Qwen2.5-7B, 35 of 37 non-tie labels (94.6\%) favor the information-advantaged strategy (Appendix~\ref{app:cross-env-details}); Llama-3.1-8B (135 games) yields 16 of 16 non-tie labels in the same direction (100\%). Llama shows fewer non-tie episodes (11.9\% vs.\ 25.9\%) but perfect directional consistency, confirming that information asymmetry---not death avoidance---drives routing signal in ALFWorld regardless of model family. The framework diagnoses this qualitatively different mechanism (DAF $= 0\%$ vs.\ $90.4\%$) without modification.
83	
84	\subsection{Baselines}
85	\label{sec:baselines}
86	
87	\begin{table}[t]
88	\centering
89	\small
90	\resizebox{\columnwidth}{!}{%
91	\begin{tabular}{@{}lccc@{}}
92	\toprule
93	Strategy & Score & 95\% CI & Death \% \\
94	\midrule
95	Always-Internal & $-39.07$ & [$-46.40$, $-32.27$] & 42.9 \\
96	Always-Deterministic & $-9.47$ & [$-14.71$, $-4.29$] & 16.3 \\
97	Random & $-22.38$ & [$-28.67$, $-15.75$] & 27.8 \\
98	Oracle & $-6.58$ & [$-11.54$, $-1.70$] & 14.3 \\
99	\midrule
100	Trained Router$^\dagger$ & $-10.70$ & [$-16.33$, $-5.27$] & 17.6 \\
101	\bottomrule
102	\end{tabular}}
103	\caption{Episode-weighted mean scores on ScienceWorld (11 task types, 20--40 episodes per type, 245 total). $\dagger$\,Single random seed (42) per episode pair; see Appendix~\ref{app:seed-robustness} for 8-seed robustness analysis. Per-task results are exploratory ($n{=}20$ episodes per task, power $\approx 50\%$ for 20\,pp effects); aggregate conclusions do not depend on individual task significance.}
104	\label{tab:baselines}
105	\end{table}
106	
107	Always-deterministic ($-9.47$) outperforms always-internal ($-39.07$) by 29.60 points. The oracle improves only to $-6.58$, with 96.3\% of decisions matching always-deterministic---an \emph{oracle degeneracy} where an always-deterministic lookup achieves 90.5\% of non-tie oracle decisions (balanced accuracy 50.0\%: perfect deterministic recall, zero internal recall).
108	
109	\subsection{Router Training: A Negative Result}
110	\label{sec:router-diagnostic}
111	
112	We probe whether counterfactual labels can train a step-level router, as a diagnostic of label informativeness. The oracle margin (2.89 points) caps routing upside. The near-chance step-level accuracy admits two interpretations: (A)~episode-level labels projected onto steps create ${\sim}$88\% uninformative signal (60.3\% pre-event neutral, 27.4\% post-event), drowning learnable patterns in noise; (B)~routing signal is genuinely task-type-level---there is no step-level pattern to learn. Directional conflict is only 0.3\% of 2{,}040 training steps, but the granularity mismatch leaves minimal signal. The text augmentation ablation (25\%--800\% via paraphrase, no improvement) and extreme class imbalance (86/95 $= 90.5\%$ deterministic-preferred) together favor Interpretation~B (non-learnability): no step-level learnable signal exists under current architectures and data regime---though alternative architectures or genuine episode-level scaling remain untested.
113	
114	An implicit router (Qwen3, LoRA; Appendix~\ref{app:router-details}) trained at three scales (0.6B, 1.7B, 4B) shows flat step-level balanced accuracy ($56$--$59\%$). At episode level, only 4B exceeds always-deterministic ($59.0 \pm 1.9\%$, $p < 0.001$, Bonferroni-corrected across 8 comparisons); 0.6B and 1.7B remain at chance. The 4B model's marginally above-chance episode-level accuracy is consistent with task-type identification rather than step-level routing signal, as confirmed by leave-one-task-type-out analysis degrading to chance (49.2\%; Appendix~\ref{app:ablations}). Episode-level independent evaluation yields $47.1 \pm 2.2\%$, below the majority-vote baseline of 50.0\%; this independent set includes held-out task types, so the below-chance result reflects cross-task transfer failure rather than overall router incompetence. Training uses episode-level splits (Appendix~\ref{app:router-details}), ensuring no within-episode leakage. The high uninformative rate connects to noisy-label learning~\citep{natarajan2013learning,northcutt2021confident,li2020dividemix}: standard ERM on labels with ${\sim}$88\% noise yields near-chance classifiers, consistent with theoretical bounds on learning from corrupted labels and empirical results in structured noise settings.
115	
116	\paragraph{End-to-end deployment.} The 4B router deployed end-to-end ($N{=}245$) scores $-12.03$ (95\% CI: $[-17.82, -6.45]$), not exceeding always-deterministic ($-9.47$). Paraphrase-based augmentation ($25\%$--$800\%$) provides no improvement; the $3.7\%$ internal-preferred base rate makes real-data collection expensive (Appendices~\ref{app:seed-robustness}--\ref{app:ablations}).
117	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "87990f20-261b-47b3-a3b4-2d5952c1dd71",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "9061f7a0-2405-4274-905a-434db2ab0d63",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe analyze 11 of ScienceWorld's 30 task types (245 episodes); the 19 excluded types (63\\%) lack actionable routing signal due to development contamination (5), taxonomic redundancy (7), or agent-floor performance (7). This scope limits generalizability: conclusions apply to the included subset, not to all ScienceWorld tasks. An anti-cherry-picking analysis confirms that death dominance holds in 18 of these 19 types, with a mean $\\Delta\\text{DR} = +38.2$\\,pp exceeding the included tasks' $+28.7$\\,pp (Appendix~\\ref{app:per-task}). Extended validation at $n{=}20$ on five representative excluded tasks confirms this direction ($\\overline{\\Delta\\text{DR}} = +32.0$\\,pp; Appendix~\\ref{app:extended-validation}). A reasoning-depth ablation ($n{=}120$) found no significant difference between internal strategy variants ($p > 0.26$; Appendix~\\ref{app:ablations}).\n\n\\subsection{Death Avoidance Decomposition}\n\\label{sec:death-decomp}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig1_daf_scatter.pdf}\n\\caption{Per-task scatter: death rate differential (internal $-$ deterministic) vs.\\ performance gap ($\\Delta_{\\text{full}}$). $r = 0.97$ (Spearman's $\\rho = 0.986$; Appendix~\\ref{app:per-task}), $p < 10^{-6}$, $n = 11$ task types. Since $\\Delta_{\\text{full}} \\approx \\delta P + \\Delta_{\\text{nd}}$ with $P$ constant, $r \\to 1$ as DAF $\\to 1$; the near-perfect correlation is a structural consequence of death dominance, not an independent finding (\\S\\ref{sec:death-decomp}).}\n\\label{fig:decomposition}\n\\end{figure}\n\nOf the 95 non-tie routing labels, 75 (78.9\\%) arise from death asymmetry: the internal strategy triggers a catastrophic $-100$ penalty while the deterministic strategy survives. This penalty-independent label fraction is the primary diagnostic metric. Of these 75, 54 are sole-signal labels (both strategies score zero without death, so death avoidance was the \\emph{sole} discriminating signal). At $P{=}0$, the 54 sole-signal labels reduce to ties, leaving 41 non-tie labels of which 21 (51.2\\%) still involve death asymmetry; the labeling function itself is penalty-independent (Algorithm~\\ref{alg:labeling}), but the practical routing value of death avoidance requires $P > 0$.\n\nOf 245 episodes, 150 (61.2\\%) are ties---neither strategy outperforms the other---indicating that routing is relevant in only 38.8\\% of episodes. Among these, death avoidance dominates. The Death Avoidance Factor, a derived penalty-dependent measure, quantifies death's contribution to the total performance gap: DAF $= 90.4\\%$ at $P{=}100$ ($\\Delta_{\\text{full}} = +29.60$, $\\Delta_{\\text{nd}} = +2.84$; 95\\% CI: $[81.1\\%, 99.0\\%]$, episode-level bootstrap, $B{=}10{,}000$). DAF varies with penalty magnitude ($50.4\\%$ at $P{=}10$; $82.6\\%$ at $P{=}50$; Appendix~\\ref{app:penalty}), confirming that the 78.9\\% label fraction provides the more robust characterization. When $\\Delta_{\\text{nd}} \\to 0$, DAF $\\to 1$ is algebraic necessity regardless of actual death dominance; conversely, when $\\Delta_{\\text{nd}} < 0$ (as in Reflexion $N{\\geq}3$; \\S\\ref{sec:agent-improvement}), DAF exceeds 100\\%, reflecting that death asymmetry more than accounts for the full gap.\n\n\\paragraph{Per-task correlation structure.}\nThe internal strategy dies in 42.9\\% of episodes versus 16.3\\% for deterministic (2.6$\\times$), consistent with the internal strategy's reliance on self-generated observations that compound prediction errors across steps. Per-task, death rate differential correlates with $\\Delta_{\\text{full}}$ ($r = 0.97$, $p < 10^{-6}$; Figure~\\ref{fig:decomposition}; Appendix~\\ref{app:correlation}). Since $P$ is constant across all task types, $\\Delta_{\\text{full}} = P \\cdot \\delta + \\Delta_{\\text{nd}}$ makes $\\Delta_{\\text{full}}$ a linear function of $\\delta$ with residual $\\Delta_{\\text{nd}}$; when DAF $\\rightarrow 1$, this residual vanishes and $r \\rightarrow 1$ by construction. The near-perfect correlation is therefore a mathematical consequence of death dominance, not an independent empirical finding. We retain it as an internal consistency check. The correlation drops below significance at $P \\leq 25$ (Appendix~\\ref{app:penalty}). Of 245 episodes, 86 are \\texttt{det\\_preferred}, 9 \\texttt{internal\\_preferred}, and 150 \\texttt{no\\_preference}.\n\n\\paragraph{Signal concentration and binary structure.}\nThe Signal Concentration Index (SCI $= 0.2147$; Appendix~\\ref{app:sci}) confirms low concentration: the top-3 task types account for only $39.8\\%$ of total death-rate differential. The aggregate 78.9\\% reflects a per-task binary structure: all 10 death-prone task types produce 100\\% death-asymmetry labels, while \\texttt{find-non-living-thing} (zero deaths, $\\Delta = +9.58$ from non-death scores) produces 0\\%. The framework thus diagnoses a binary property (``is this environment death-dominated?'') rather than a continuous routing signal. Removing \\texttt{find-non-living-thing} raises the label fraction to 100\\% and yields DAF $\\geq$100\\% ($\\Delta_\\text{nd} \\leq 0$; death avoidance fully accounts for the routing gap among remaining task types; Appendix~\\ref{app:loto-daf}).\n\n\\paragraph{Sensitivity and seed robustness.}\nNon-clustered episode-level bootstrap ($B = 10{,}000$) yields 95\\% CI $[81.1\\%, 99.0\\%]$ for DAF, independent of cluster assumptions, with Cohen's $d = 3.02$ (interpret cautiously given $K{=}11$ task types). Leave-one-task-out analysis confirms stability (label fraction range: 75.9\\%--78.9\\%; Appendix~\\ref{app:loto-daf}); an independent seed replication ($N{=}220$) yields DAF $= 89.7\\%$, within 0.7~pp (Appendix~\\ref{app:seed-robustness}). As a conservative check, wild cluster bootstrap treating each task type as a cluster yields $p = 0.002$; however, with $K{=}11$ clusters this test falls below the $K{\\geq}20$--$40$ threshold recommended for reliable inference~\\citep{cameron-2008,webb-2023}, so we rely on the non-clustered bootstrap as primary. All 28 death-prone tasks share the same direction (Appendices~\\ref{app:wild-cluster}--\\ref{app:per-task-ci}).\n\n\\subsection{Multi-Model Validation}\n\\label{sec:cross-model}\n\nA Llama-3.1-8B-Instruct~\\citep{llama3-2024} cross-model replication across all 11 task types ($N{=}220$) confirms that death dominance replicates across model families: internal death rate $41.4\\%$ vs.\\ deterministic $11.4\\%$ (death-rate differential $+30.0$~pp), DAF $= 88.2\\%$ (95\\% CI: $[80.2\\%, 95.1\\%]$; $\\Delta_{\\text{full}} = +33.17$, $\\Delta_{\\text{nd}} = +3.9$), with direction consistency 10/10 on death-prone tasks, 83 deterministic-preferred, 3 internal-preferred (1.4\\%, all death-asymmetry reversals), and 134 no-preference labels.\nBoth models exhibit nearly identical internal vulnerability (${\\sim}$42\\%: Qwen $42.9\\%$, Llama $41.4\\%$), confirming that death-prone failure is empirically dominated; the differential magnitude varies ($+26.5$~pp Qwen, $+30.0$~pp Llama) because deterministic strategy safety is model-dependent ($16.3\\%$ vs.\\ $11.4\\%$).\n\\texttt{identify-life-stages-1} shows cross-model precision matching ($55\\%$/$10\\%$/$+45$~pp in both models).\n\\texttt{find-non-living-thing} shows zero deaths in both models, consistent with its majority-class answer distribution (Appendix~\\ref{app:per-task}). Cross-model routing transfer is vacuously correct: Llama produces zero internal-preferred episodes, so Qwen-derived routing rules (always-deterministic) trivially match, confirming that routing signal is environment-determined rather than model-specific.\nA third model family, Gemma-2-9B-it~\\citep{gemma2-2024} (sliding window attention, vs.\\ full attention in Qwen/Llama), independently confirms the pattern: DAF${=}89.7\\%$ (95\\% CI $[79.5\\%, 98.4\\%]$; $N{=}220$), with all 10 death-prone task types showing positive $\\Delta$DR (Appendix~\\ref{app:cross-model}). Three architecturally distinct models thus converge on DAF $88$--$90\\%$ (spread 2.2~pp); $10{\\times}$ scaling to 72B (\\S\\ref{sec:agent-improvement}) confirms persistence across capability levels.\n\n\\subsection{Agent Improvement Baselines}\n\\label{sec:agent-improvement}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{@{}lrr@{}}\n\\toprule\nCondition & Death\\% & $N$ \\\\\n\\midrule\nSingle-trial baseline & 42.9 & 245 \\\\\nReflexion ($3{\\times}$) & 31.4 & 220 \\\\\nQwen2.5-72B ($10{\\times}$) & 30.6 & 255 \\\\\nDeterministic baseline & 16.3 & 245 \\\\\n\\midrule\n\\multicolumn{3}{@{}l}{\\textit{10 death-prone tasks only:}} \\\\\nDeath-prone baseline & 48.0 & 200 \\\\\nRetry ($5{\\times}$) & 43.5 & 200 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Internal-strategy death rates under agent improvement methods. Top: all 11 tasks (72B: independently collected at both internal and deterministic). Bottom: 10 death-prone tasks (\\texttt{find-non-living-thing} excluded, 0\\% death at all scales). All interventions reduce death rate but none approaches deterministic-level safety.}\n\\label{tab:agent-improvement}\n\\end{table}\n\nWe test whether agent-level improvement reduces death dominance (Table~\\ref{tab:agent-improvement}). Retry ($N{=}5$ attempts without self-correction) yields marginal reduction on death-prone tasks ($43.5\\%$ vs.\\ $48.0\\%$ baseline, $\\Delta = -4.5$~pp). Reflexion~\\citep{reflexion-2023} (verbal self-reflection between trials) reduces death to 31.4\\% across all 11 tasks by rescuing 29.3\\% of first-trial deaths, but the gap to deterministic remains 15.1~pp; on the 10 death-prone tasks, Reflexion achieves ${\\sim}$35\\%. Under Reflexion ($N{=}3$, matched-episode analysis), $\\Delta_{\\text{nd}} = -0.47$, yielding DAF $> 100\\%$: the deterministic advantage is entirely attributable to death avoidance, and in non-death episodes the self-correcting agent slightly outperforms the deterministic baseline. Scaling to Qwen2.5-72B ($10{\\times}$ parameters; both internal and deterministic strategies independently collected at 72B, 255 episodes across all 11 task types) reduces death rate to $30.6\\%$. The 72B deterministic strategy achieves $2.75\\%$ death rate ($\\Delta\\text{DR} = +27.8$~pp), and $\\Delta_{\\text{nd}} = +2.28$, yielding DAF $= 92.4\\%$ (7B: $90.4\\%$); scaling lowers death rate but leaves death dominance intact.\n\n\\paragraph{Dose-response analysis.}\nWe extend both interventions to $N{=}5$ trials on death-prone tasks ($n{=}200$; Figure~\\ref{fig:dose-response}). Retry is nearly flat ($48.0\\% \\to 43.5\\%$, $\\Delta = -4.5$~pp over five trials). Reflexion drops steeply to $34.0\\%$ at $N{=}3$ ($\\Delta = -13.5$~pp, $z = 2.75$, $p = 0.003$) then stabilizes ($34$--$36.5\\%$ for $N \\geq 3$, pairwise $p > 0.5$). With $n{=}200$ paired episodes, the minimum detectable effect is ${\\sim}8$~pp ($\\alpha = 0.05$, 80\\% power): the key $N{=}1{\\to}3$ decline is well-powered; the stabilization claim ($N{=}3{\\to}5$, $+1.0$~pp) is also supported, since a ${\\geq}8$~pp improvement would be detected. We characterize this as suggestive evidence of a Reflexion ceiling rather than a conclusive demonstration. Retry's per-trial conditional death rate stays constant at ${\\sim}48\\%$; Reflexion's declines to ${\\sim}31\\%$ by Trial~3 (per-task breakdown in Appendix~\\ref{app:dose-response}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/dose_response.pdf}\n\\caption{Death rate as a function of trial count ($N$) for Retry and Reflexion on 10 death-prone tasks ($n{=}200$). Retry (blue) is nearly flat; Reflexion (red) drops steeply through $N{=}3$ then shows no statistically detectable improvement beyond $N{=}3$ (Wilson CIs for $N{=}3,4,5$ overlap substantially). Horizontal lines: 72B scaling baseline ($30.6\\%$, all 11 tasks) and deterministic baseline ($16.3\\%$). Error bands: Wilson 95\\% CIs.}\n\\label{fig:dose-response}\n\\end{figure}\n\n\\subsection{Cross-Environment Boundary Probes}\n\\label{sec:math-contrast}\n\\label{sec:cross-env}\n\nWe examine MATH and ALFWorld as boundary probes---not cross-domain validation---testing framework applicability across environments that instantiate ``deterministic computation'' differently (oracle simulator, code interpreter, admissible-action enumeration; see operationalization in \\S\\ref{sec:problem-setup}).\n\n\\paragraph{MATH.} On MATH Level~4--5~\\citep{math-2021} ($N{=}795$, code interpreter), internal reasoning and code interpretation achieve near-identical accuracy ($73.5\\%$ vs.\\ $73.0\\%$, McNemar $p = 0.81$), with 84.4\\% no-preference. Without catastrophic failure, no routing signal emerges.\n\n\\paragraph{ALFWorld.} ALFWorld~\\citep{alfworld-2021} (6 task types, 135 games) provides the deterministic strategy with admissible actions---an information asymmetry rather than a computation mode switch, with no death mechanism ($\\delta = 0$, DAF $= 0\\%$). With Qwen2.5-7B, 35 of 37 non-tie labels (94.6\\%) favor the information-advantaged strategy (Appendix~\\ref{app:cross-env-details}); Llama-3.1-8B (135 games) yields 16 of 16 non-tie labels in the same direction (100\\%). Llama shows fewer non-tie episodes (11.9\\% vs.\\ 25.9\\%) but perfect directional consistency, confirming that information asymmetry---not death avoidance---drives routing signal in ALFWorld regardless of model family. The framework diagnoses this qualitatively different mechanism (DAF $= 0\\%$ vs.\\ $90.4\\%$) without modification.\n\n\\subsection{Baselines}\n\\label{sec:baselines}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nStrategy & Score & 95\\% CI & Death \\% \\\\\n\\midrule\nAlways-Internal & $-39.07$ & [$-46.40$, $-32.27$] & 42.9 \\\\\nAlways-Deterministic & $-9.47$ & [$-14.71$, $-4.29$] & 16.3 \\\\\nRandom & $-22.38$ & [$-28.67$, $-15.75$] & 27.8 \\\\\nOracle & $-6.58$ & [$-11.54$, $-1.70$] & 14.3 \\\\\n\\midrule\nTrained Router$^\\dagger$ & $-10.70$ & [$-16.33$, $-5.27$] & 17.6 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Episode-weighted mean scores on ScienceWorld (11 task types, 20--40 episodes per type, 245 total). $\\dagger$\\,Single random seed (42) per episode pair; see Appendix~\\ref{app:seed-robustness} for 8-seed robustness analysis. Per-task results are exploratory ($n{=}20$ episodes per task, power $\\approx 50\\%$ for 20\\,pp effects); aggregate conclusions do not depend on individual task significance.}\n\\label{tab:baselines}\n\\end{table}\n\nAlways-deterministic ($-9.47$) outperforms always-internal ($-39.07$) by 29.60 points. The oracle improves only to $-6.58$, with 96.3\\% of decisions matching always-deterministic---an \\emph{oracle degeneracy} where an always-deterministic lookup achieves 90.5\\% of non-tie oracle decisions (balanced accuracy 50.0\\%: perfect deterministic recall, zero internal recall).\n\n\\subsection{Router Training: A Negative Result}\n\\label{sec:router-diagnostic}\n\nWe probe whether counterfactual labels can train a step-level router, as a diagnostic of label informativeness. The oracle margin (2.89 points) caps routing upside. The near-chance step-level accuracy admits two interpretations: (A)~episode-level labels projected onto steps create ${\\sim}$88\\% uninformative signal (60.3\\% pre-event neutral, 27.4\\% post-event), drowning learnable patterns in noise; (B)~routing signal is genuinely task-type-level---there is no step-level pattern to learn. Directional conflict is only 0.3\\% of 2{,}040 training steps, but the granularity mismatch leaves minimal signal. The text augmentation ablation (25\\%--800\\% via paraphrase, no improvement) and extreme class imbalance (86/95 $= 90.5\\%$ deterministic-preferred) together favor Interpretation~B (non-learnability): no step-level learnable signal exists under current architectures and data regime---though alternative architectures or genuine episode-level scaling remain untested.\n\nAn implicit router (Qwen3, LoRA; Appendix~\\ref{app:router-details}) trained at three scales (0.6B, 1.7B, 4B) shows flat step-level balanced accuracy ($56$--$59\\%$). At episode level, only 4B exceeds always-deterministic ($59.0 \\pm 1.9\\%$, $p < 0.001$, Bonferroni-corrected across 8 comparisons); 0.6B and 1.7B remain at chance. The 4B model's marginally above-chance episode-level accuracy is consistent with task-type identification rather than step-level routing signal, as confirmed by leave-one-task-type-out analysis degrading to chance (49.2\\%; Appendix~\\ref{app:ablations}). Episode-level independent evaluation yields $47.1 \\pm 2.2\\%$, below the majority-vote baseline of 50.0\\%; this independent set includes held-out task types, so the below-chance result reflects cross-task transfer failure rather than overall router incompetence. Training uses episode-level splits (Appendix~\\ref{app:router-details}), ensuring no within-episode leakage. The high uninformative rate connects to noisy-label learning~\\citep{natarajan2013learning,northcutt2021confident,li2020dividemix}: standard ERM on labels with ${\\sim}$88\\% noise yields near-chance classifiers, consistent with theoretical bounds on learning from corrupted labels and empirical results in structured noise settings.\n\n\\paragraph{End-to-end deployment.} The 4B router deployed end-to-end ($N{=}245$) scores $-12.03$ (95\\% CI: $[-17.82, -6.45]$), not exceeding always-deterministic ($-9.47$). Paraphrase-based augmentation ($25\\%$--$800\\%$) provides no improvement; the $3.7\\%$ internal-preferred base rate makes real-data collection expensive (Appendices~\\ref{app:seed-robustness}--\\ref{app:ablations}).\n",
      "numLines": 117,
      "startLine": 1,
      "totalLines": 117
    }
  },
  "sourceToolAssistantUUID": "87990f20-261b-47b3-a3b4-2d5952c1dd71",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-21T13:43:45.182Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WVvVXpSbhKNxiHyR647LKm`</summary>

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
  "parentUuid": "9061f7a0-2405-4274-905a-434db2ab0d63",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "867ee533-a264-4a4d-ba7c-019312eac292",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 32 · 2026-05-21T13:43:45.193Z_

<details><summary>↩ Tool result · `toolu_01WVvVXpSbhKNxiHyR647LKm`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Why the router fails: task-type-level signal.}
5	The router diagnostic (\S\ref{sec:router-diagnostic}) reveals a structural mismatch: death avoidance is a task-type-level binary property (10/11 types carry death risk), but step-level features correlate weakly because death risk depends on multi-step trajectories. The 4B router improves at episode level ($59.0\%$) without step-level gains ($56$--$59\%$), confirming task-type classification; cross-task-type transfer yields chance accuracy (49.2\%; Appendix~\ref{app:ablations}).
6	
7	\paragraph{Non-triviality of death dominance.}
8	While death dominance follows from the penalty structure (\S\ref{sec:daf}), three specific consequences were not predictable a priori: (i)~$10{\times}$ scaling to 72B fails to eliminate it (DAF${}= 92.4\%$); (ii)~Reflexion self-correction yields DAF${}>100\%$, meaning death avoidance \emph{more} than accounts for the full gap; (iii)~a 0.5B model shows \emph{reduced} death rate ($13.3\%$; $n{=}15$) because it is too weak to reach dangerous states, revealing an inverted-U capability--vulnerability relationship. All four intervention axes leave ${\geq}12$~pp residual gaps to deterministic safety (Appendix~\ref{sec:threshold-routing}); cross-model stability ($36$--$43\%$ internal DR across three families) confirms death vulnerability is a task-environment property. More aggressive interventions remain untested, so we characterize a ceiling, not a universal bound.
9	
10	\paragraph{Anatomy of catastrophic failure.}
11	All 105 internal-strategy deaths trace to a single grounding failure: misuse of the answer-submission action (\texttt{focus on}) as a general interaction command. The internal strategy enters catastrophic states more frequently (105 vs.\ 40 deaths), not through different within-episode behavior; grounding interventions reduce but do not eliminate death (Appendix~\ref{app:failure-modes}--\ref{app:grounding-ablation}).
12	
13	\paragraph{Practical implications.}
14	Death dominance diagnosis is actionable: a ${\sim}$50-episode pilot classifies the environment before committing to router development (Appendix~\ref{app:decision-framework}). When $f_{\text{death}} > 75\%$ (validated in ScienceWorld), deterministic routing matches or exceeds learned alternatives; below $50\%$, genuine opportunities warrant router development.
15	
16	
17	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "867ee533-a264-4a4d-ba7c-019312eac292",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "3816cc1a-a557-46e1-aaf1-931e6da83a5b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Why the router fails: task-type-level signal.}\nThe router diagnostic (\\S\\ref{sec:router-diagnostic}) reveals a structural mismatch: death avoidance is a task-type-level binary property (10/11 types carry death risk), but step-level features correlate weakly because death risk depends on multi-step trajectories. The 4B router improves at episode level ($59.0\\%$) without step-level gains ($56$--$59\\%$), confirming task-type classification; cross-task-type transfer yields chance accuracy (49.2\\%; Appendix~\\ref{app:ablations}).\n\n\\paragraph{Non-triviality of death dominance.}\nWhile death dominance follows from the penalty structure (\\S\\ref{sec:daf}), three specific consequences were not predictable a priori: (i)~$10{\\times}$ scaling to 72B fails to eliminate it (DAF${}= 92.4\\%$); (ii)~Reflexion self-correction yields DAF${}>100\\%$, meaning death avoidance \\emph{more} than accounts for the full gap; (iii)~a 0.5B model shows \\emph{reduced} death rate ($13.3\\%$; $n{=}15$) because it is too weak to reach dangerous states, revealing an inverted-U capability--vulnerability relationship. All four intervention axes leave ${\\geq}12$~pp residual gaps to deterministic safety (Appendix~\\ref{sec:threshold-routing}); cross-model stability ($36$--$43\\%$ internal DR across three families) confirms death vulnerability is a task-environment property. More aggressive interventions remain untested, so we characterize a ceiling, not a universal bound.\n\n\\paragraph{Anatomy of catastrophic failure.}\nAll 105 internal-strategy deaths trace to a single grounding failure: misuse of the answer-submission action (\\texttt{focus on}) as a general interaction command. The internal strategy enters catastrophic states more frequently (105 vs.\\ 40 deaths), not through different within-episode behavior; grounding interventions reduce but do not eliminate death (Appendix~\\ref{app:failure-modes}--\\ref{app:grounding-ablation}).\n\n\\paragraph{Practical implications.}\nDeath dominance diagnosis is actionable: a ${\\sim}$50-episode pilot classifies the environment before committing to router development (Appendix~\\ref{app:decision-framework}). When $f_{\\text{death}} > 75\\%$ (validated in ScienceWorld), deterministic routing matches or exceeds learned alternatives; below $50\\%$, genuine opportunities warrant router development.\n\n\n",
      "numLines": 17,
      "startLine": 1,
      "totalLines": 17
    }
  },
  "sourceToolAssistantUUID": "867ee533-a264-4a4d-ba7c-019312eac292",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-21T13:43:45.617Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GNXTQdso61SoehE9nqqVna`</summary>

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
  "parentUuid": "3816cc1a-a557-46e1-aaf1-931e6da83a5b",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "6cf23212-60a5-4139-83e8-a819669c6814",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 34 · 2026-05-21T13:43:45.640Z_

<details><summary>↩ Tool result · `toolu_01GNXTQdso61SoehE9nqqVna`</summary>

```text
1	\section{Conclusion}
2	
3	In ScienceWorld, death avoidance alone accounts for 78.9\% of non-tie routing labels, stable across three model families (DAF${=}88$--$90\%$); our episode-level counterfactual framework diagnoses this before any router is built, challenging the assumption of diverse signal sources. Cross-environment probes confirm generality; a ${\sim}$50-episode pilot suffices for build-vs-buy decisions in new environments.
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6cf23212-60a5-4139-83e8-a819669c6814",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "f4178a56-cc0b-490a-a294-66f5932dd449",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\nIn ScienceWorld, death avoidance alone accounts for 78.9\\% of non-tie routing labels, stable across three model families (DAF${=}88$--$90\\%$); our episode-level counterfactual framework diagnoses this before any router is built, challenging the assumption of diverse signal sources. Cross-environment probes confirm generality; a ${\\sim}$50-episode pilot suffices for build-vs-buy decisions in new environments.\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  },
  "sourceToolAssistantUUID": "6cf23212-60a5-4139-83e8-a819669c6814",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-21T13:43:46.142Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RxeuR4VFnzEy9wcDyi3mLf`</summary>

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
  "parentUuid": "f4178a56-cc0b-490a-a294-66f5932dd449",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "0585d0b5-af02-4841-b6e5-290de6e709de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 36 · 2026-05-21T13:43:46.485Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LNCPABhqbFK5t8P9xsSHdm`</summary>

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
  "parentUuid": "0585d0b5-af02-4841-b6e5-290de6e709de",
  "isSidechain": false,
  "requestId": "req_011CbFp7DosLroYUNUo1yNQi",
  "type": "assistant",
  "uuid": "dcb49032-00b2-483b-bdfd-d1a1fbaabbd1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KUdaHe1jCXUHAiXEHGorbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11966,
      "cache_read_input_tokens": 37330,
      "output_tokens": 720,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11966,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 720,
          "cache_read_input_tokens": 37330,
          "cache_creation_input_tokens": 11966,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11966
          },
          "type": "message"
        }
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

_source line 37_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 15 warnin…",
  "leafUuid": "78debc0a-5db1-4657-8e93-79396e16e8ac",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 38_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Tool result

_source line 39 · 2026-05-21T13:43:46.703Z_

<details><summary>↩ Tool result · `toolu_01RxeuR4VFnzEy9wcDyi3mLf`</summary>

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
17	\usepackage{tcolorbox}
18	\tcbuselibrary{listings,breakable}
19	
20	\hypersetup{pdfauthor={},pdftitle={}}
21	
22	\title{Death Avoidance as the Dominant Routing Signal:\\A Counterfactual Analysis on ScienceWorld}
23	
24	\author{Anonymous}
25	
26	\begin{document}
27	\maketitle
28	
29	\input{abstract}
30	\input{introduction}
31	\input{method}
32	\input{experiments}
33	\input{related_work}
34	\input{discussion}
35	\input{conclusion}
36	
37	\section*{Limitations}
38	
39	\paragraph{Environmental scope.}
40	Our primary analysis uses a single environment (ScienceWorld, 11 of 30 task types) with one backbone (Qwen2.5-7B-Instruct), though extended validation of representative excluded tasks confirms the pattern (Appendix~\ref{app:extended-validation}). The $-100$ death penalty amplifies DAF; environments with softer penalties would exhibit lower DAF values (Appendix~\ref{app:penalty}). The 19 excluded task types (63\%) lack routing signal because both strategies typically time out within 30 steps; increasing the step budget could surface non-death-dominated signal that our current setup does not capture. Cross-environment analyses on MATH and ALFWorld (\S\ref{sec:cross-env}, \S\ref{sec:discussion}) provide preliminary supporting evidence but do not conclusively establish generalization. A Llama-3.1-8B-Instruct cross-model replication (11 task types, $N{=}220$; \S\ref{sec:cross-model}) shows death dominance replicates with direction consistency 10/10 while vulnerability magnitude varies ($+30.0$~pp vs.\ Qwen $+26.5$~pp), though both models are in the 7--8B parameter range; Qwen2.5-72B ($10{\times}$ scale) reduces death rate but does not eliminate death dominance (\S\ref{sec:agent-improvement}); validation beyond 72B remains future work. Our quantitative results (DAF $= 90.4\%$, label fractions) are specific to ScienceWorld; the framework's generality claim is methodological (the diagnostic procedure applies to any environment with asymmetric fatal outcomes), not empirical (the specific percentages may differ across environments).
41	
42	\paragraph{Methodological constraints.}
43	Our internal-reasoning baseline uses single-pass ReAct~\citep{react-2023}. Reflexion~\citep{reflexion-2023} reduces death rate from 42.9\% to 31.4\% (\S\ref{sec:agent-improvement}), but more aggressive self-correction or Tree-of-Thought backtracking~\citep{tot-2023} may further reduce internal death rates. Episode-level labels assign a single routing preference to entire episodes, which may be suboptimal for individual steps (particularly those preceding death events). However, of 2{,}040 training steps only 0.3\% exhibit strict directional conflict (step-level oracle opposite to episode label); the remaining apparent mislabeling consists of episode labels applied to steps where neither strategy has a step-level advantage (60.3\% pre-event neutral). The issue is granularity mismatch---applying correct-direction labels to uninformative steps---not directional error. Training on pure-strategy trajectories also introduces distribution shift at deployment~\citep{dagger-2011}. Under mixed-strategy routing with oracle death prediction, switching to deterministic at the step before death could reduce the internal death rate; even under optimistic assumptions (perfect step-level death prediction), a residual gap of ${>}10$~pp between strategies is expected, as fatal trajectories involve cumulative hallucination errors preceding the death event. More broadly, projecting episode-level labels onto 10--50 sequential steps with path-dependent state introduces compounding error: early routing decisions alter the state trajectory, potentially invalidating later labels derived from the episode outcome.
44	
45	\paragraph{Statistical limitations.}
46	Episodes within the same task type are not fully independent because they share environment dynamics, though they use different random seeds. Cluster bootstrap with $K{=}11$ task-type clusters yields wider CIs ($[73.3\%, 100.0\%]$); with $K < 40$ clusters, these should be interpreted cautiously~\citep{cameron-2008,webb-2023}. A wild cluster bootstrap ($K{=}11$, $p < 0.001$; Appendix~\ref{app:wild-cluster}) and 100\% directional consistency across all 28 death-prone tasks (Appendix~\ref{app:per-task-ci}) mitigate this concern.
47	
48	\paragraph{Pure-strategy upper bound.}
49	Our counterfactual analysis compares pure strategies (always-internal vs.\ always-deterministic). In mixed routing, the router can selectively invoke deterministic mode on high-risk steps, potentially reducing death asymmetry. Thus, DAF${=}90.4\%$ represents an upper bound on death avoidance's contribution to optimized routing; the actual contribution under mixed strategies may be lower.
50	
51	\paragraph{Diagnostic scope.}
52	Our framework is diagnostic rather than prescriptive: it identifies what drives routing decisions but does not optimize the routing policy itself. Extending the counterfactual decomposition to prescribe optimal mixed-strategy routing---for example, by combining DAF analysis with online policy learning---is a natural next step.
53	
54	\section*{Ethics Statement}
55	
56	This work uses ScienceWorld \citep{scienceworld-2022}, a publicly available text-based simulation environment, and does not involve human subjects or private data. All evaluation environments (ScienceWorld, ALFWorld, MATH) are released under permissive open-source licenses (Apache 2.0 / MIT). All models used (Qwen2.5 family, Llama-3.1-8B, Gemma-2-9B-it) are publicly available for research use. All language models are accessed via standard APIs or publicly released weights. Experiments were conducted on 2$\times$ NVIDIA RTX 5090 (32GB) and 4$\times$ NVIDIA RTX 6000 PRO (96GB), totaling approximately 200 GPU-hours, comprising ${\sim}$140 hours for episode collection (counterfactual inference across three 7--9B model families plus Qwen2.5-72B backbone scaling, Reflexion and retry baselines, and cross-environment validation on ALFWorld and MATH), ${\sim}$35 hours for router training (LoRA fine-tuning of Qwen3-0.6B/1.7B/4B across 4--8 seeds per scale, including augmentation and ablation variants), and ${\sim}$25 hours for evaluation and analysis. Code and data will be released upon acceptance.
57	
58	\bibliography{references}
59	
60	\appendix
61	
62	\noindent\textbf{Appendix Overview.}
63	\hyperref[app:sci]{A.~Signal Concentration Index} $\cdot$
64	\hyperref[app:labeling]{B.~Labeling Quality Audit} $\cdot$
65	\hyperref[app:per-task]{C.~Per-Task Decomposition} $\cdot$
66	\hyperref[app:correlation]{D.~Correlation Robustness} $\cdot$
67	\hyperref[app:wild-cluster]{E.~Cluster Bootstrap Sensitivity} $\cdot$
68	\hyperref[app:per-task-ci]{F.~Per-Task CIs} $\cdot$
69	\hyperref[app:loto-daf]{G.~Leave-One-Task-Out DAF} $\cdot$
70	\hyperref[app:dose-response]{H.~Dose-Response Breakdown} $\cdot$
71	\hyperref[app:router-details]{I.~Router Training Details} $\cdot$
72	\hyperref[app:seed-robustness]{J.~Seed Robustness} $\cdot$
73	\hyperref[app:penalty]{K.~Penalty Sensitivity} $\cdot$
74	\hyperref[app:cross-env-details]{L.~Cross-Environment Details} $\cdot$
75	\hyperref[app:cross-model]{M.~Cross-Model Verification} $\cdot$
76	\hyperref[app:failure-modes]{N.~Failure Mode Analysis} $\cdot$
77	\hyperref[app:grounding-ablation]{O.~Grounding Ablation} $\cdot$
78	\hyperref[app:ablations]{P.~Ablation Studies} $\cdot$
79	\hyperref[sec:threshold-routing]{Q.~Threshold Routing} $\cdot$
80	\hyperref[app:decision-framework]{R.~Decision Framework} $\cdot$
81	\hyperref[app:extended-validation]{S.~Extended Validation} $\cdot$
82	\hyperref[app:prompt-templates]{T.~Agent Prompt Templates}
83	
84	\section{Signal Concentration Index}
85	\label{app:sci}
86	
87	Let $K$ denote the number of task types and $c_k$ the contribution of task type $k$ to the aggregate routing signal, defined as the fraction of total death-rate differential attributable to task $k$:
88	\begin{equation}
89	    c_k = \frac{n_k \cdot \delta_k}{\sum_{j=1}^{K} n_j \cdot \delta_j}
90	\end{equation}
91	where $n_k$ is the number of episodes and $\delta_k = d_k^{\tt int} - d_k^{\tt det}$ is the per-task death-rate differential. The SCI is the Gini coefficient over $\{c_1, \ldots, c_K\}$:
92	\begin{equation}
93	    \text{SCI} = \frac{\sum_{i=1}^K \sum_{j=1}^K |c_i - c_j|}{2K \sum_{k=1}^K c_k}
94	\end{equation}
95	
96	\section{Labeling Quality Audit}
97	\label{app:labeling}
98	
99	\begin{algorithm}[t]
100	\caption{Episode-Level Counterfactual Labeling}
101	\label{alg:labeling}
102	\begin{algorithmic}[1]
103	\REQUIRE Task instance $t$, computation modes $\mathcal{M} = \{{\tt int}, {\tt det}\}$
104	\ENSURE Label $\ell \in \{{\tt det\text{-}pref}, {\tt int\text{-}pref}, {\tt no\text{-}pref}\}$
105	\FOR{each $m \in \mathcal{M}$}
106	    \STATE Run episode $\tau_m$ with pure-strategy $m$
107	    \STATE Record score $s_m$ and death indicator $d_m$
108	\ENDFOR
109	\IF{$d_{\tt int} = 1$ \AND $d_{\tt det} = 0$}
110	    \STATE $\ell \leftarrow {\tt det\text{-}pref}$ \COMMENT{death asymmetry}
111	\ELSIF{$d_{\tt int} = 0$ \AND $d_{\tt det} = 1$}
112	    \STATE $\ell \leftarrow {\tt int\text{-}pref}$ \COMMENT{death asymmetry}
113	\ELSIF{$d_{\tt int} = d_{\tt det} = 1$}
114	    \STATE $\ell \leftarrow {\tt no\text{-}pref}$ \COMMENT{both dead}
115	\ELSIF{$s_{\tt det} > s_{\tt int}$}
116	    \STATE $\ell \leftarrow {\tt det\text{-}pref}$ \COMMENT{score comparison}
117	\ELSIF{$s_{\tt int} > s_{\tt det}$}
118	    \STATE $\ell \leftarrow {\tt int\text{-}pref}$ \COMMENT{score comparison}
119	\ELSE
120	    \STATE $\ell \leftarrow {\tt no\text{-}pref}$ \COMMENT{tied alive}
121	\ENDIF
122	\RETURN $\ell$
123	\end{algorithmic}
124	\end{algorithm}
125	
126	Note that episode-level labels are used to evaluate step-level predictions, introducing a granularity mismatch rather than independent validation. A potential concern is oracle circularity: whether episode-level labels reflect tie-breaking artifacts rather than genuine computation mode differences. We audit all 245 labels. Of the 150 \texttt{no\_preference} labels (61.2\%), 115 (46.9\%) are both-alive ties and 35 (14.3\%) are both-dead, all excluded from router training. The remaining 95 training labels are entirely genuine: 75 from death asymmetry (70 deterministic-preferred, 5 internal-preferred) and 20 from score comparison with both strategies surviving (16 deterministic-preferred, 4 internal-preferred). Zero labels depend on tie-breaking. Retraining the router using only death-asymmetry labels yields step-level balanced accuracy of 57.3\%, within 1$\sigma$ of the full-label retrain (57.6 $\pm$ 0.5\%, step-level Trainer evaluation); score-comparison labels contribute negligible additional signal. (Step-level metrics are used here for the relative comparison; as shown in \S\ref{sec:router-diagnostic}, absolute generalization to new episodes is near chance.) The 97.4\% step-level tie rate (\S\ref{sec:collection}) further motivates episode-level over step-level labeling.
127	
128	\section{Per-Task Decomposition}
129	\label{app:per-task}
130	We use ScienceWorld v1.2.3~\citep{scienceworld-2022}.
131	We select 11 of ScienceWorld's 30 task types for analysis. Types are excluded when they were used for pipeline development (5 tasks, standard hold-out practice), are taxonomically redundant with a retained family representative (7 tasks), or exhibit near-zero task progress under both strategies (7 tasks, agent capability floor).\footnote{Excluded tasks exhibit even stronger death dominance than included tasks ($\Delta\text{DR} = +38.2$\,pp vs.\ $+28.7$\,pp; Table~\ref{tab:excluded-death}).}
132	
133	\begin{table}[h]
134	\centering
135	\scriptsize
136	\setlength{\tabcolsep}{2.5pt}
137	\begin{tabular}{@{}lrrccc@{}}
138	\toprule
139	Task & $n$ & $\Delta_\text{full}$ & D\%\textsubscript{int} & D\%\textsubscript{det} & D / I / N \\
140	\midrule
141	id-life-stages-1       & 20  & $+47.50$ & 55   & 10   & 9 / 0 / 11  \\
142	lifespan-long          & 25  & $+44.00$ & 56   & 16   & 11 / 1 / 13 \\
143	lifespan-l-then-s      & 20  & $+40.80$ & 45   & 10   & 8 / 1 / 11  \\
144	inclined-plane         & 20  & $+36.00$ & 55   & 20   & 7 / 0 / 13  \\
145	freeze                 & 20  & $+30.50$ & 55   & 25   & 6 / 0 / 14  \\
146	meas-melt-point        & 20  & $+30.05$ & 55   & 25   & 6 / 0 / 14  \\
147	id-life-stages-2       & 20  & $+30.00$ & 50   & 20   & 6 / 0 / 14  \\
148	find-animal            & 20  & $+26.65$ & 50   & 25   & 5 / 0 / 15  \\
149	grow-fruit             & 20  & $+25.10$ & 45   & 20   & 6 / 1 / 13  \\
150	chem-mix               & 20  & $+21.80$ & 45   & 25   & 6 / 2 / 12  \\
151	\midrule
152	find-non-living-thing$^\dagger$ & 40 & $+9.58$ & 0  & 0    & 16 / 4 / 20 \\
153	\midrule
154	\textbf{All (11 tasks)} & \textbf{245} & $\mathbf{+29.60}$ & \textbf{42.9} & \textbf{16.3} & \textbf{86 / 9 / 150} \\
155	\bottomrule
156	\end{tabular}
157	\caption{Per-task decomposition of the death avoidance effect. D\%: death rate for internal (int) and deterministic (det) strategies. D/I/N: episode labels (det-preferred / internal-preferred / no-preference). Sorted by $\Delta_{\text{full}}$ descending. The \textit{All} row is an episode-weighted aggregate across 245 episodes. $\dagger$\,Only task with zero deaths under both strategies; $n{=}40$ because data was collected in two batches, with the second batch adding 20 episodes to increase statistical power for this zero-death outlier.}
158	\label{tab:per-task}
159	\end{table}
160	
161	\paragraph{Task selection and anti-cherry-picking.}
162	Eighteen of the 19 excluded task types (95\%) exhibit death-asymmetric patterns (Table~\ref{tab:excluded-death}): internal-reasoning death rates range from 40\% to 60\% (mean 53.9\%), while deterministic death rates range from 0\% to 40\% (mean 15.8\%), yielding a mean death-rate differential of $+38.2$\,pp, exceeding the $+28.7$\,pp for included tasks. The included subset is thus \emph{less} death-asymmetric than the excluded subset, the opposite of what a cherry-picking hypothesis would predict. The sole exception is \texttt{grow-plant}, an intrinsically safe task with zero deaths under both strategies, paralleling \texttt{find-non-living-thing} in the included set. The 19 excluded tasks fall into three independently motivated categories: five used during pipeline development (standard hold-out practice), seven taxonomically redundant with included family representatives (deduplication), and seven where the 7B backbone achieves near-zero task progress regardless of strategy (agent capability floor). In no case was a task excluded because death dominance was absent. Exclusion is driven by absence of non-death routing signal ($\Delta_{\text{nd}} = 0$ for 53\% of excluded tasks) and standard deduplication practices. \texttt{find-non-living-thing} serves as an internal counterexample: zero deaths under both strategies yet included because it exhibits non-death routing signal ($\Delta_{\text{full}} = +9.58$ entirely from score differences), and deterministic is not always preferred (4 of 20 non-tie labels favor internal).
163	
164	\begin{table}[t]
165	\centering
166	\scriptsize
167	\setlength{\tabcolsep}{2pt}
168	\begin{tabular}{@{}llrcccl@{}}
169	\toprule
170	Task & Grp & $n$ & D\%\textsubscript{int} & D\%\textsubscript{det} & $\Delta$DR & Excl.\ reason \\
171	\midrule
172	boil                          & A & 20 & 50 & 20 & $+30$ & dev set \\
173	change-state-of-matter        & A & 20 & 55 & 15 & $+40$ & dev set \\
174	chem-mix-paint-secondary      & A & 20 & 45 & 10 & $+35$ & dev set \\
175	grow-plant                    & A & 20 &  0 &  0 & $\phantom{+}0$  & dev set \\
176	melt                          & A & 20 & 55 & 15 & $+40$ & dev set \\
177	\midrule
178	chem-mix-paint-tertiary       & B &  5 & 40 & 20 & $+20$ & family redundancy \\
179	find-living-thing             & B &  5 & 60 & 20 & $+40$ & family redundancy \\
180	find-plant                    & B &  5 & 60 &  0 & $+60$ & family redundancy \\
181	inclined-friction-named       & B &  5 & 60 & 20 & $+40$ & family redundancy \\
182	inclined-friction-unnamed     & B &  5 & 60 &  0 & $+60$ & family redundancy \\
183	lifespan-shortest             & B &  5 & 60 & 40 & $+20$ & family redundancy \\
184	measure-melt-known            & B &  5 & 60 &  0 & $+60$ & family redundancy \\
185	\midrule
186	mendelian-known               & C &  5 & 60 & 20 & $+40$ & agent floor \\
187	mendelian-unknown             & C &  5 & 60 & 40 & $+20$ & agent floor \\
188	power-component               & C &  5 & 60 & 20 & $+40$ & agent floor \\
189	power-renewable               & C &  5 & 60 &  0 & $+60$ & agent floor \\
190	test-conductivity             & C &  5 & 60 & 20 & $+40$ & agent floor \\
191	test-conductivity-unknown     & C &  5 & 60 & 20 & $+40$ & agent floor \\
192	use-thermometer               & C &  5 & 60 & 20 & $+40$ & agent floor \\
193	\midrule
194	\textbf{Mean (19 excluded)}   &   &    & \textbf{53.9} & \textbf{15.8} & $\mathbf{+38.2}$ & \\
195	\textit{cf.\ included (11)}   &   &    & \textit{46.5} & \textit{17.8} & $\textit{+28.7}$ & \\
196	\bottomrule
197	\end{tabular}
198	\caption{Death-rate analysis of all 19 excluded task types. D\%: death rate (score $\leq -100$). $\Delta$DR = D\%\textsubscript{int} $-$ D\%\textsubscript{det}. 18 of 19 excluded tasks (95\%) exhibit positive death asymmetry ($\Delta$DR $\geq +20$\,pp). Exclusion groups: A = development set (excluded to prevent circular evaluation), B = taxonomically redundant with an included family representative, C = agent-floor tasks (backbone achieves near-zero progress regardless of strategy). The mean $\Delta$DR among excluded tasks ($+38.2$\,pp) exceeds that of included tasks ($+28.7$\,pp), confirming that task selection does not bias toward death-prone tasks. Group B--C estimates are based on $n{=}5$ prescreening episodes per task and should be interpreted as directional evidence rather than precise rate estimates.}
199	\label{tab:excluded-death}
200	\end{table}
201	
202	\section{Correlation Robustness}
203	\label{app:correlation}
204	
205	The Pearson $r = 0.9698$ reported in \S\ref{sec:death-decomp} is robust across multiple diagnostics. Spearman rank correlation is $\rho = 0.986$ ($p = 2.4 \times 10^{-8}$); the relationship is not driven by outliers or non-linearity. A nonparametric bootstrap (10{,}000 resamples) yields 95\% CI $[0.952, 0.995]$.
206	
207	\begin{table}[h]
208	\centering
209	\small
210	\begin{tabular}{@{}lr@{}}
211	\toprule
212	Task removed & $r_{\text{LOO}}$ \\
213	\midrule
214	id-life-stages-1       & 0.963 \\
215	lifespan-long          & 0.969 \\
216	lifespan-l-then-s      & 0.976 \\
217	inclined-plane         & 0.969 \\
218	freeze                 & 0.971 \\
219	meas-melt-point        & 0.972 \\
220	id-life-stages-2       & 0.972 \\
221	find-animal            & 0.970 \\
222	grow-fruit             & 0.973 \\
223	chem-mix               & 0.969 \\
224	find-non-living-thing  & 0.980 \\
225	\bottomrule
226	\end{tabular}
227	\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\ $\Delta_{\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}
228	\label{tab:loo}
229	\end{table}
230	
231	\section{Cluster Bootstrap Sensitivity Analysis}
232	\label{app:wild-cluster}
233	
234	With $K{=}11$ task-type clusters, cluster bootstrap falls well below the $K{\geq}20$--30 recommended for reliable inference \citep{cameron-2008,webb-2023}. The narrower CIs obtained reflect known small-sample bias toward underestimation of variance, not tighter inference.
235	
236	Episodes within the same task type share environment dynamics, raising the concern that the effective sample size is closer to $K$ (task types) than $N$ (episodes). We address this with cluster-robust inference treating each task type as a cluster ($K{=}11$, all 11 included task types, 245 episodes).
237	
238	\begin{table}[h]
239	\centering
240	\small
241	\begin{tabular}{@{}lcc@{}}
242	\toprule
243	Method & $p$-value & 95\% CI \\
244	\midrule
245	Cluster-robust $t$-test ($t{=}10.0$, df$=$10) & $< 0.001$ & $[0.73, 1.00]$ \\
246	Wild cluster bootstrap ($B{=}9{,}999$) & $< 0.001$ & $[0.73, 1.00]$ \\
247	Exact permutation ($2{,}048$ perms) & $0.002$ & --- \\
248	Sign test & $< 0.001$ & --- \\
249	\bottomrule
250	\end{tabular}
251	\caption{Cluster-level tests of death-rate asymmetry ($K{=}11$ task clusters, 245 episodes). 10 of 11 clusters show internal DR $>$ deterministic DR; the sole exception (\texttt{find-non-living-thing}) has zero deaths under both strategies. Cohen's $d = 3.02$. The exact permutation $p = 0.002$ ($4/2{,}048$) reflects the near-unanimous directional consistency.}
252	\label{tab:wild-cluster}
253	\end{table}
254	
255	\noindent All methods confirm significance with $p < 0.01$, and the 95\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.
256	
257	We retain this analysis for transparency; readers should rely on the non-clustered episode-level bootstrap (\S\ref{sec:death-decomp}) as the primary inference.
258	
259	\section{Per-Task Death Rate Confidence Intervals}
260	\label{app:per-task-ci}
261	
262	We compute bootstrap 95\% CIs for the death-rate differential ($\Delta\text{DR} = \text{DR}_{\text{int}} - \text{DR}_{\text{det}}$) for all 30 ScienceWorld task types. Of 30 tasks, 28 are death-prone (at least one death under either strategy); the remaining 2 (\texttt{grow-plant}, \texttt{find-non-living-thing}) have zero deaths under both strategies.
263	
264	Across all 28 death-prone tasks, internal DR exceeds deterministic DR without exception (100\% directional consistency). The pooled death-rate differential is $+37.3\%$ (95\% CI: $[29.7\%, 44.4\%]$). Fifteen of 28 tasks are individually significant (CI excludes zero); the 13 non-significant tasks all have $n{=}5$ prescreening episodes, where statistical power is insufficient to detect even large effects (e.g., a task with $\Delta\text{DR} = +40$\,pp at $n{=}5$ has a CI of $\pm 43$\,pp). The universal directional consistency, combined with the pooled significance, confirms that death asymmetry is not driven by a subset of outlier tasks.
265	
266	\section{Leave-One-Task-Out DAF Sensitivity}
267	\label{app:loto-daf}
268	
269	\begin{table}[h]
270	\centering
271	\small
272	\caption{Leave-one-task-out DAF sensitivity (penalty-independent label fraction). Among the 10 death-prone tasks, removing any single task changes DAF by at most 3.0\,pp (range: 75.9\%--78.9\%). Removing \emph{Find Non-Living Thing}, the sole death-free task that contributes all 20 score-comparison episodes, raises DAF to 100\% by construction.}
273	\label{tab:loto-daf}
274	\begin{tabular}{lrrr}
275	\toprule
276	Removed Task & $N_\text{rem}$ & DAF (\%) & $\Delta$ (pp) \\
277	\midrule
278	(none, full) & 245 & 78.9 & --- \\
279	\midrule
280	Find Non-Living$^\dagger$ & 205 & 100.0 & +21.1 \\
281	Lifespan Longest & 220 & 75.9 & $-$3.0 \\
282	Life Stages 1 & 225 & 76.7 & $-$2.2 \\
283	Lifespan Long+Short & 225 & 76.7 & $-$2.2 \\
284	Chemistry Mix & 225 & 77.0 & $-$1.9 \\
285	Grow Fruit & 225 & 77.3 & $-$1.7 \\
286	Inclined Plane Angle & 225 & 77.3 & $-$1.7 \\
287	Freeze & 225 & 77.5 & $-$1.4 \\
288	Life Stages 2 & 225 & 77.5 & $-$1.4 \\
289	Melt Pt Unknown & 225 & 77.5 & $-$1.4 \\
290	Find Animal & 225 & 77.8 & $-$1.2 \\
291	\bottomrule
292	\end{tabular}
293	
294	\vspace{2pt}
295	{\footnotesize $^\dagger$Only death-free task; contributes all score-comparison labels. Sorted by $|\Delta|$ descending.}
296	\end{table}
297	
298	\section{Per-Task Dose-Response Breakdown}
299	\label{app:dose-response}
300	
301	Table~\ref{tab:dose-response-detail} reports per-task death rates for Reflexion at $N{=}3$, 4, and 5 on the 10 death-prone tasks ($n{=}20$ episodes per task). Per-task variance is high (up to 25\,pp range for \texttt{measure-melting-point}), but the aggregate smooths to a 2.5\,pp band, confirming that the stabilization conclusion is robust at the aggregate level despite task-level noise. \texttt{freeze} is consistently the hardest task (50--60\% DR across all $N$).
302	
303	\begin{table}[h]
304	\centering
305	\small
306	\caption{Per-task death rates (\%) for Reflexion at $N{=}3$, 4, 5 on 10 death-prone tasks ($n{=}20$ per task). Aggregate death rates confirm stabilization at $N \geq 3$ (range: $34.0$--$36.5\%$).}
307	\label{tab:dose-response-detail}
308	\begin{tabular}{@{}lrrr@{}}
309	\toprule
310	Task & $N{=}3$ & $N{=}4$ & $N{=}5$ \\
311	\midrule
312	chemistry-mix & 25.0 & 35.0 & 20.0 \\
313	find-animal & 45.0 & 30.0 & 45.0 \\
314	freeze & 50.0 & 50.0 & 60.0 \\
315	grow-fruit & 30.0 & 25.0 & 25.0 \\
316	identify-life-stages-1 & 35.0 & 35.0 & 35.0 \\
317	identify-life-stages-2 & 25.0 & 25.0 & 30.0 \\
318	inclined-plane-angle & 20.0 & 30.0 & 35.0 \\
319	lifespan-longest & 45.0 & 40.0 & 40.0 \\
320	lifespan-long+short & 30.0 & 45.0 & 35.0 \\
321	measure-melting-pt & 35.0 & 50.0 & 25.0 \\
322	\midrule
323	\textbf{Aggregate} & \textbf{34.0} & \textbf{36.5} & \textbf{35.0} \\
324	\bottomrule
325	\end{tabular}
326	\end{table}
327	
328	\section{Router Training Details}
329	\label{app:router-details}
330	
331	We use Qwen3-1.7B for the router to avoid circular dependency with the Qwen2.5-7B data-generating model.
332	
333	With gradient accumulation of 1 (effective batch size 4), routing performance is highly sensitive to the evaluation split; this suggests overfitting to specific train/validation partition boundaries. With gradient accumulation of 8 (effective batch size 32), step-level performance stabilizes across splits (${\sim}54\%$ balanced accuracy). All reported results use gradient accumulation 8.
334	
335	Under step-level evaluation with a fixed data split, cross-seed balanced accuracy ranges from 52.7\% to 58.1\%, but internal recall varies from 51.5\% to 81.8\%, which reflects threshold sensitivity. However, episode-level evaluation reveals that this apparent discrimination does not generalize: balanced accuracy drops to $47.1 \pm 2.2\%$ across 8 cross-split seeds (Appendix~\ref{app:seed-robustness}). Deployed end-to-end, the trained router allocates 97.0\% of episodes to deterministic computation with 17.6\% death rate, and misrouting cost (death from internally-routed episodes) exceeds the benefit of correctly routing rare internal-preferred cases.
336	
337	\paragraph{Evaluation methods.} All results use \emph{generation-based evaluation}: the model generates a routing label as text (\texttt{enable\_thinking=False}), parsed for classification. We evaluate at two granularities: \emph{step-level} (steps from the same episode may appear in both train and validation sets) and \emph{episode-level} (entire episodes held out). Step-level accuracy ($54.1 \pm 5.4\%$) exceeds chance (the router captures some signal), but episode-level accuracy ($47.1 \pm 2.2\%$, below chance) shows this does not generalize to unseen episodes. Paraphrase-based text augmentation (Appendix~\ref{app:seed-robustness}) provides no improvement; real-data scaling remains open. Always-deterministic is trivially near-optimal given DAF $= 90.4\%$. The main text (\S\ref{sec:router-diagnostic}) reports controlled 4-seed results at three scales; the model-size ablation (Appendix~\ref{app:ablations}) provides further detail.
338	
339	\begin{table}[h]
340	\centering
341	\small
342	\resizebox{\columnwidth}{!}{%
343	\begin{tabular}{@{}lcc@{}}
344	\toprule
345	Hyperparameter & Classification Head & Implicit Router \\
346	\midrule
347	Base model & Qwen3-1.7B & Qwen3-1.7B \\
348	Architecture & Linear + LoRA & SFT + LoRA \\
349	LoRA $r$ / $\alpha$ & 16 / 32 & 16 / 32 \\
350	Learning rate & 2e-5 & 2e-4 \\
351	Optimizer & AdamW & AdamW \\
352	Epochs & 3 & 3 \\
353	Batch size (per device) & 4 & 4 \\
354	Gradient accumulation & 8 & 8 \\
355	Warmup ratio & 0.1 & 0.1 \\
356	Weight decay & 0.01 & 0.01 \\
357	Max sequence length & 512 & 512 \\
358	Seeds & \{42\} & \{42, 123, 456, 789\} \\
359	\bottomrule
360	\end{tabular}}
361	\caption{Router training hyperparameters. Both architectures use the same base model with LoRA adaptation. The classification head degenerates across all configurations; the implicit router results are reported as 4-seed mean$\pm$std.}
362	\label{tab:hyperparams}
363	\end{table}
364	
365	\paragraph{Agent inference parameters.}
366	For ScienceWorld, each agent step uses temperature $T{=}0.3$ and maximum generation length of 256 tokens, served via vLLM v0.21.0. Top-$p$ is left at the vLLM default of $1.0$ (no nucleus sampling). For MATH, the agent uses greedy decoding ($T{=}0.0$) with a maximum of 2{,}048 tokens per generation. For ALFWorld, we use $T{=}0.3$ with 256 maximum tokens. All three environments use Qwen2.5-7B-Instruct~\citep{qwen25-2024} as the backbone.
367	
368	\section{Seed Robustness}
369	\label{app:seed-robustness}
370	
371	We assess router generalization at two evaluation granularities: \emph{step-level}, where steps from the same episode may appear in both train and validation sets, and \emph{episode-level}, where entire episodes are held out. Both use cross-split evaluation (seeds $\{42, \ldots, 49\}$, 8 seeds total), where the data partition and training seed both vary. Table~\ref{tab:seed-robustness} reports per-seed results.
372	
373	\begin{table}[h]
374	\centering
375	\small
376	\begin{tabular}{@{}llcc@{}}
377	\toprule
378	Eval.\ Granularity & Seed & Bal.\ Acc.\ (\%) \\
379	\midrule
380	Step-level & 42 & 57.06 \\
381	(same-episode & 43 & 63.99 \\
382	leakage) & 44 & 55.43 \\
383	 & 45 & 56.14 \\
384	 & 46 & 55.45 \\
385	 & 47 & 50.08 \\
386	 & 48 & 48.03 \\
387	 & 49 & 59.30 \\
388	\cmidrule{2-3}
389	 & Mean$\pm$std & $54.1 \pm 5.4$ \\
390	\midrule
391	Episode-level & 42 & 48.1 \\
392	(held-out & 43 & 47.9 \\
393	episodes) & 44 & 49.6 \\
394	 & 45 & 49.4 \\
395	 & 46 & 48.5 \\
396	 & 47 & 43.1 \\
397	 & 48 & 45.4 \\
398	 & 49 & 44.8 \\
399	\cmidrule{2-3}
400	 & Mean$\pm$std & $47.1 \pm 2.2$ \\
401	\midrule
402	\multicolumn{2}{@{}l}{Always-det (= majority-vote)} & 50.0 \\
403	\bottomrule
404	\end{tabular}
405	\caption{Per-seed router performance under cross-split evaluation (8 seeds, generation-based, \texttt{enable\_thinking=False}). Step-level evaluation allows steps from the same episode in both train and validation sets (same-episode leakage). Episode-level evaluation holds out entire episodes; the resulting $47.1 \pm 2.2\%$ is below the 50\% chance baseline. A text augmentation ablation (Table~\ref{tab:text-augmentation}) confirms this failure persists under the current data distribution and augmentation regime.}
406	\label{tab:seed-robustness}
407	\end{table}
408	
409	The contrast between step-level ($54.1 \pm 5.4\%$) and episode-level ($47.1 \pm 2.2\%$) evaluation reveals a generalization gap: the step-level signal likely reflects memorization of episode-specific context (enabled by same-episode leakage) rather than extraction of generalizable routing features. At episode level, the router performs below chance across all 8 seeds (range: 43.1\%--49.6\%). Paraphrase-based text augmentation (Table~\ref{tab:text-augmentation}) from 25\% to 800\% ($32{\times}$ range) provides no improvement, converging to the always-deterministic baseline ($50\%$). Paraphrase augmentation inflates the majority class without generating novel routing patterns; genuine episode-level scaling (collecting more counterfactual pairs) remains an open question. With DAF $= 90.4\%$ and all task types deterministic-majority (86:9 label ratio), always-deterministic trivially solves the episode-level routing problem, leaving the step-level router with no exploitable signal under current architectures.
410	
411	\paragraph{Text augmentation ablation.} To test whether the episode-level generalization failure stems from data scarcity, we vary training set size from 25\% to 800\% of the original via paraphrase-based text augmentation (synonym substitution + template variation on step observations), holding the episode-level validation set fixed. This tests augmentation-based scaling, not genuine episode-level scaling (which would require new counterfactual collections). Table~\ref{tab:text-augmentation} reports the results.
412	
413	\begin{table}[h]
414	\centering
415	\small
416	\begin{tabular}{@{}rccc@{}}
417	\toprule
418	Scale & Samples & Det\% & Ep.\ Bal.\ Acc.\ (\%) \\
419	\midrule
420	25\% & 433 & ${\sim}90$ & $49.5 \pm 0.3$ \\
421	50\% & 867 & ${\sim}90$ & $51.5$ \\
422	100\% & 1{,}735 & 89.6 & $49.9 \pm 0.1$ \\
423	200\% & 3{,}470 & 94.2 & $50.0 \pm 0.0$ \\
424	800\% & 13{,}880 & ${\sim}97.7$ & $51.0 \pm 1.1$ \\
425	\midrule
426	Always-det & --- & --- & 50.0 \\
427	\bottomrule
428	\end{tabular}
429	\caption{Text augmentation ablation: episode-level balanced accuracy across training set sizes (25\%--800\% of original via paraphrase, $32{\times}$ range). Internal recall $= 0.0$ at all scales (complete majority-class collapse). Det\%: fraction of deterministic-preferred labels in training data. The 50\% scale is a single seed; all others report mean$\pm$std across seeds.}
430	\label{tab:text-augmentation}
431	\end{table}
432	
433	All scales hover at ${\sim}50\%$ episode-level balanced accuracy (equivalent to the always-deterministic baseline), with no monotonic improvement as data increases. Augmentation-based scaling provides no improvement at any scale; however, episode-level minority-class diversity remains a potential confound that cannot be resolved without collecting more internal-preferred episodes. The ground-truth internal-preferred rate (9/245 $= 3.7\%$) means collecting 50 internal-preferred episodes would require approximately 1{,}350 paired episodes at current environment dynamics, a $5.5{\times}$ expansion with diminishing return on a $9.6\%$ signal. The failure points to a limitation of the current data distribution: when DAF $= 90.4\%$ and all task types are deterministic-majority (86:9 label ratio), the episode-level routing problem is trivially solved by always choosing deterministic, and the step-level router finds no exploitable signal under the current architecture and data regime.
434	
435	Augmentation disproportionately increases the majority (deterministic) class: Det\% rises from 89.6\% at 100\% to 94.2\% at 200\% and ${\sim}97.7\%$ at 800\%. However, the complete collapse to majority-class prediction (internal recall $= 0.0$) occurs even at the smallest unaugmented scale (25\%, ${\sim}90\%$ det); this is not an augmentation artifact. Balanced accuracy corrects for class imbalance by averaging per-class recall, so the metric itself is not biased by the skew.
436	
437	Decomposition metrics are stable under bootstrap resampling ($B{=}10{,}000$ resamples of the 245-episode dataset): DAF $= 90.4\% \pm 4.2\%$ (95\% CI $[81.1\%, 99.0\%]$); Pearson $r = 0.975 \pm 0.011$ (95\% CI $[0.952, 0.995]$). The death avoidance dominance finding is robust to both resampling and split perturbation.
438	
439	\paragraph{Per-task-type evaluation breakdown.} To test whether the router learns transferable routing strategies or merely task-type classification, we evaluate existing checkpoints (8 seeds) separately on each of the 11 task types. Of the 11 task types, 7 have \emph{all-deterministic} labels (no internal-preferred episodes exist), making balanced accuracy undefined; the router has nothing to learn beyond the trivial always-deterministic default. For the remaining 4 task types where both classes are present, balanced accuracy ranges from 50.0\% to 73.0\%, but this apparent signal does not indicate cross-task-type routing transfer: the router is effectively classifying task types (which correlate with death risk) rather than extracting a generalizable routing strategy. This complements the text augmentation ablation: routing signal does not transfer across task types because the signal \emph{is} the task type, i.e., whether a given task carries death risk. The 4B capacity scaling result (Appendix~\ref{app:ablations}) suggests capacity is one factor, but even 4B's $59.0\%$ episode-level accuracy does not demonstrate cross-task-type transfer.
440	
441	\section{Penalty Sensitivity Analysis}
442	\label{app:penalty}
443	
444	\begin{table}[h]
445	\centering
446	\small
447	\begin{tabular}{@{}rrr@{}}
448	\toprule
449	$P$ & DAF($P$) & 95\% CI \\
450	\midrule
451	0 & 7.4\% & [$-39.4$, $82.5$] \\
452	1 & 14.8\% & [$-28.6$, $89.6$] \\
453	5 & 35.4\% & [$-1.8$, $92.7$] \\
454	10 & 50.4\% & [$18.5$, $93.3$] \\
455	25 & 70.7\% & [$48.0$, $96.3$] \\
456	50 & 82.6\% & [$67.2$, $98.2$] \\
457	100\textsuperscript{*} & 90.4\% & [$81.1$, $99.0$] \\
458	200 & 94.9\% & [$89.9$, $99.5$] \\
459	500 & 97.9\% & [$95.7$, $99.8$] \\
460	\bottomrule
461	\end{tabular}
462	\caption{Sensitivity of DAF to death penalty magnitude $P$. DAF$(P) = 1 - \Delta_{\text{nd}} / \Delta_{\text{full}}(P)$, where $\Delta_{\text{full}}(P) \approx \delta \cdot P + \Delta_{\text{nd}}$, $\delta = 0.2653$ is the death-rate differential, and $\Delta_{\text{nd}} = 2.84$ (strict neither-died filtering). Recomputed from 245 episode-level data; bootstrap 95\% CIs ($B{=}10{,}000$). \textsuperscript{*}Default setting.}
463	\label{tab:penalty-sensitivity}
464	\end{table}
465	
466	The non-death score gap $\Delta_{\text{nd}} = 2.84$ is invariant across penalty levels; it depends only on surviving-episode performance, not on $P$. As $P$ increases, $\Delta_{\text{full}}$ grows ($16.33$ at $P{=}50$, $29.60$ at $P{=}100$, $56.13$ at $P{=}200$) while $\Delta_{\text{nd}}$ remains fixed, mechanically increasing DAF.
467	
468	\paragraph{Mechanism boundary: death specificity.}
469	The $r = 0.97$ correlation between per-task death-rate differential and $\Delta_{\text{full}}$ is specific to catastrophic death (score $= -100$). Broader failure definitions dissolve the correlation entirely: defining ``failure'' as any non-positive score ($T{=}0$) yields $r = -0.13$ ($p = 0.70$), because non-death episodes show near-zero performance differential between strategies ($\Delta_{\text{nd}} = 2.84$). Table~\ref{tab:penalty-correlation} quantifies this specificity across penalty magnitudes.
470	
471	\begin{table}[h]
472	\centering
473	\small
474	\begin{tabular}{@{}rccl@{}}
475	\toprule
476	$P$ & $r$ & $p$ & Sig.\ ($\alpha{=}0.05$) \\
477	\midrule
478	1 & $-0.44$ & $0.178$ & No \\
479	5 & $-0.29$ & $0.382$ & No \\
480	10 & $-0.08$ & $0.813$ & No \\
481	25 & $0.51$ & $0.108$ & No \\
482	50 & $0.86$ & $0.0006$ & Yes \\
483	100\textsuperscript{*} & $0.97$ & $8 \times 10^{-7}$ & Yes \\
484	200 & $0.99$ & $1 \times 10^{-9}$ & Yes \\
485	\bottomrule
486	\end{tabular}
487	\caption{Pearson $r$ between per-task death-rate differential and $\Delta_{\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \textsuperscript{*}Default ScienceWorld setting.}
488	\label{tab:penalty-correlation}
489	\end{table}
490	
491	This sharpens our central finding: death is not merely the dominant component of routing signal; it is effectively the \emph{only} component that generates differential routing signal in ScienceWorld. At low penalties, the death contribution is small and $\Delta_{\text{full}}$ reduces to $\Delta_{\text{nd}} \approx 2.84$, which is near-uniform across task types ($\text{mean non-death gap} = -1.19$ excluding the \texttt{find-non-living-thing} outlier); consequently, death-rate differential has no predictive power. As $P$ increases, the death term dominates $\Delta_{\text{full}}$, and the correlation sharpens because death rates \emph{are} the performance gap. The DAF values in Table~\ref{tab:penalty-sensitivity} increase monotonically with $P$, but this is a mathematical consequence of the decomposition ($\text{DAF} = \delta P / (\delta P + \Delta_{\text{nd}})$), not evidence of mechanism robustness.
492	
493	\section{Cross-Environment Details}
494	\label{app:cross-env-details}
495	
496	Figure~\ref{fig:signal-reversal} and Table~\ref{tab:cross-env} summarize the label distributions across all three environments.
497	
498	\begin{figure}[h]
499	\centering
500	\includegraphics[width=\columnwidth]{figures/signal_reversal.pdf}
501	\caption{Cross-environment label distributions. ScienceWorld and ALFWorld both show deterministic preference, but through different mechanisms: death avoidance (ScienceWorld) vs.\ information asymmetry from admissible-action access (ALFWorld). MATH shows balanced labels, confirming no routing signal without catastrophic failure.}
502	\label{fig:signal-reversal}
503	\end{figure}
504	
505	\begin{table}[h]
506	\centering
507	\small
508	\resizebox{\columnwidth}{!}{%
509	\begin{tabular}{@{}lccccc@{}}
510	\toprule
511	Environment & $N$ & Det\% & Int\% & NoPref\% & Death? \\
512	\midrule
513	ScienceWorld & 245 & 35.1 & 3.7 & 61.2 & Yes ($-100$) \\
514	MATH & 795 & 7.3 & 8.3 & 84.4 & No \\
515	ALFWorld & 135 & 25.9 & 1.5 & 72.6 & No\textsuperscript{$\dagger$} \\
516	\bottomrule
517	\end{tabular}}
518	\caption{Cross-environment label distribution. ``Deterministic'' denotes qualitatively different computation modes: ScienceWorld = oracle simulator with ground-truth state; MATH = Python code interpreter; ALFWorld = admissible-action enumeration. $\dagger$\,ALFWorld's deterministic advantage stems from information asymmetry, not death avoidance.}
519	\label{tab:cross-env}
520	\end{table}
521	
522	Table~\ref{tab:alfworld-pertask} provides the per-task-type breakdown for ALFWorld. Unlike ScienceWorld, ALFWorld has no death mechanism ($\delta = 0$, DAF $= 0\%$); the entire performance gap $\Delta_{\text{full}}$ reflects information asymmetry from admissible-action access. \texttt{pick\_and\_place} shows the strongest effect ($\Delta = 0.563$, 18 of 32 episodes det-preferred), while \texttt{pick\_two\_obj\_and\_place} shows the weakest ($\Delta = 0.087$), consistent with multi-object tasks requiring more sequential reasoning that admissible actions alone cannot resolve. Only \texttt{pick\_heat\_then\_place} has a 95\% CI crossing zero ($n{=}16$).
523	
524	\begin{table}[h]
525	\centering
526	\scriptsize
527	\setlength{\tabcolsep}{2.5pt}
528	\begin{tabular}{@{}lrcccc@{}}
529	\toprule
530	Task Type & $n$ & Succ\%\textsubscript{int} & Succ\%\textsubscript{det} & D / I / N & $\Delta_{\text{full}}$ \\
531	\midrule
532	pick\_and\_place       & 32 & 0.0  & 56.3 & 18 / 0 / 14 & $+0.563$ \\
533	look\_at\_obj\_in\_light & 13 & 15.4 & 38.5 & 3 / 0 / 10  & $+0.231$ \\
534	pick\_cool\_then\_place & 24 & 0.0  & 16.7 & 4 / 0 / 20  & $+0.167$ \\
535	pick\_clean\_then\_place & 27 & 3.7  & 18.5 & 5 / 1 / 21  & $+0.148$ \\
536	pick\_heat\_then\_place & 16 & 6.3  & 18.8 & 3 / 1 / 12  & $+0.125$ \\
537	pick\_two\_obj\_and\_place & 23 & 0.0 & 8.7  & 2 / 0 / 21  & $+0.087$ \\
538	\midrule
539	\textbf{All (6 types)} & \textbf{135} & \textbf{3.0} & \textbf{27.4} & \textbf{35 / 2 / 98} & $\mathbf{+0.244}$ \\
540	\bottomrule
541	\end{tabular}
542	\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\Delta_{\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\Delta_{\text{full}}$ descending.}
543	\label{tab:alfworld-pertask}
544	\end{table}
545	
546	\paragraph{MATH subset composition.}
547	The $N{=}795$ MATH problems span two categories from the MATH test set~\citep{math-2021} (Levels 4--5): Algebra (585, 73.6\%) and Counting \& Probability (210, 26.4\%). The category imbalance reflects the relative sizes in the original test set.
548	
549	\section{Cross-Model Verification}
550	\label{app:cross-model}
551	
552	We replicate the counterfactual analysis with Llama-3.1-8B-Instruct across all 11 task types ($N{=}220$ episode pairs, 20 per type; Table~\ref{tab:cross-model-detail}).
553	The internal strategy dies in $41.4\%$ of episodes versus $11.4\%$ for deterministic (death-rate differential $+30.0$~pp), with 83 deterministic-preferred, 3 internal-preferred (1.4\%, all death-asymmetry reversals), and 134 no-preference labels.
554	Both models exhibit nearly identical internal vulnerability (${\sim}$42\%: Qwen $42.9\%$, Llama $41.4\%$), confirming that death-prone failure is empirically dominated by the task environment rather than model-specific factors. The differential magnitude varies ($+26.5$~pp Qwen, $+30.0$~pp Llama) because deterministic strategy safety is model-dependent ($16.3\%$ vs.\ $11.4\%$), but directional consistency is 100\% (10/10 death-prone tasks in both models).
555	\texttt{identify-life-stages-1} shows cross-model precision matching ($55\%$/$10\%$/$+45$~pp in both models).
556	\texttt{find-non-living-thing} shows zero deaths in both models, consistent with its majority-class answer distribution.
557	
558	\begin{table}[h]
559	\centering
560	\small
561	\begin{tabular}{@{}lrrrl@{}}
562	\toprule
563	Task & Int\% & Det\% & $\Delta$\,pp & D / I / N \\
564	\midrule
565	identify-life-stages-1 & 55 & 10 & +45 & 9 / 0 / 11 \\
566	freeze & 45 & 0 & +45 & 9 / 0 / 11 \\
567	grow-fruit & 45 & 5 & +40 & 8 / 0 / 12 \\
568	identify-life-stages-2 & 45 & 5 & +40 & 8 / 0 / 12 \\
569	measure-melting-point & 50 & 15 & +35 & 9 / 0 / 11 \\
570	lifespan-longest & 35 & 5 & +30 & 7 / 1 / 12 \\
571	lifespan-l-then-s & 50 & 20 & +30 & 6 / 0 / 14 \\
572	chemistry-mix & 45 & 20 & +25 & 5 / 0 / 15 \\
573	inclined-plane & 45 & 20 & +25 & 6 / 0 / 14 \\
574	find-animal & 40 & 25 & +15 & 6 / 2 / 12 \\
575	find-non-living-thing & 0 & 0 & 0 & 10 / 0 / 10 \\
576	\midrule
577	\textbf{Aggregate} & \textbf{41.4} & \textbf{11.4} & \textbf{+30.0} & \textbf{83 / 3 / 134} \\
578	\bottomrule
579	\end{tabular}
580	\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\Delta$ DR descending.}
581	\label{tab:cross-model-detail}
582	\end{table}
583	
584	\paragraph{Cross-model and cross-environment summary.}
585	Table~\ref{tab:cross-model-env} consolidates replication results across model families and environments.
586	
587	\begin{table}[h]
588	\centering
589	\small
590	\resizebox{\columnwidth}{!}{%
591	\begin{tabular}{llcrrrccc}
592	\toprule
593	Model & Environment & $n$ & Int DR & Det DR & $\Delta$DR & DAF & DAF 95\% CI & Signal \\
594	\midrule
595	Qwen2.5-7B & ScienceWorld & 245 & 42.9\% & 16.3\% & +26.5 & 90.4\% & [81.1, 99.0] & death \\
596	Llama-3.1-8B & ScienceWorld & 220 & 41.4\% & 11.4\% & +30.0 & 88.2\% & [80.2, 95.1] & death \\
597	Gemma-2-9B-it & ScienceWorld & 220 & 36.4\% & 14.1\% & +22.3 & 89.7\% & [79.5, 98.4] & death \\
598	Qwen2.5-72B & ScienceWorld & 255 & 30.6\% & 2.75\% & +27.8 & 92.4\% & --- & death \\
599	\midrule
600	Qwen2.5-7B & ALFWorld & 135 & 0\% & 0\% & 0 & 0\% & --- & info-asym \\
601	Llama-3.1-8B & ALFWorld & 135 & 0\% & 0\% & 0 & 0\% & --- & info-asym \\
602	\midrule
603	Qwen2.5-7B & MATH & 795 & N/A & N/A & N/A & N/A & N/A & none \\
604	\bottomrule
605	\end{tabular}}
606	\caption{Cross-model and cross-environment replication summary. \textbf{ScienceWorld}: death dominance replicates across three model families in the 7--9B range and persists under $10{\times}$ scaling (72B); DAF 95\% CIs from non-clustered episode-level bootstrap ($B{=}10{,}000$). \textbf{ALFWorld}: DAF $= 0\%$ (no death mechanism); routing signal arises from information asymmetry. \textbf{MATH}: no routing signal without catastrophic failure. Signal column: diagnosed routing mechanism. DR = death rate. Gemma-2's wider CI reflects one zero-death task type (\texttt{find-non-living-thing}); excluding it yields DAF $= 99.9\%$ $[99.7, 100.0]$.}
607	\label{tab:cross-model-env}
608	\end{table}
609	
610	\section{Failure Mode Analysis}
611	\label{app:failure-modes}
612	
613	All 105 internal-strategy deaths (100\%) are triggered by the same action pattern: \texttt{focus on [object]}. In ScienceWorld, \texttt{focus on} is the answer-submission action (equivalent to ``this is my final answer''); the LLM agent systematically misuses it as a general interaction or exploration command, and applies it to irrelevant targets (rooms, doors, inventory items). Each such execution submits an incorrect answer and triggers the $-100$ death penalty. Within death episodes, both strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$); the internal strategy's higher death count (105 vs.\ 40 for deterministic) reflects how often each strategy enters catastrophic states, not different action selection within those states.
614	
615	Manual inspection identifies four failure categories: (A) no task awareness, where the agent executes \texttt{focus on} without reading the task; (B) task-aware but lacking action grounding, where the agent correctly identifies the objective but cannot map it to valid action primitives; (D) genuine attempts with execution failure; and (E) initial progress wasted by early errors. Category B dominates: agents demonstrate task comprehension but systematically fail to translate it into correct ScienceWorld actions. This taxonomy was produced by a single annotator; no inter-annotator agreement was computed. The categories are intended as qualitative illustrations, not as formal labels with reliability guarantees.
616	\label{tab:death-taxonomy}
617	
618	\paragraph{Representative examples.}
619	\emph{Category A} (no task awareness): In a \texttt{chemistry-mix} episode, the agent immediately executes \texttt{focus on kitchen}, \texttt{focus on door}, \texttt{focus on inventory} without reading the task, dying on the first \texttt{focus on} call. \emph{Category B} (comprehension without grounding): In a \texttt{lifespan-longest-lived} episode, the agent correctly identifies that it must compare animal lifespans and reasons about which animal lives longest, but then executes \texttt{focus on oak tree} (a non-animal object in the room) instead of navigating to find the target animal, triggering death.
620	
621	\paragraph{Action distribution analysis.}
622	Figure~\ref{fig:death-action-dist} shows the action distribution in death versus non-death episodes for the internal strategy; both are dominated by \texttt{connect} actions, with \texttt{focus on} moderately more frequent in death episodes ($5.4\%$ vs.\ $3.4\%$). Crucially, Figure~\ref{fig:death-comparison} reveals that within death episodes, internal and deterministic strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$). The survival gap (105 vs.\ 40 deaths) therefore reflects how often each strategy enters catastrophic states, not how it behaves within those states. Among fatal \texttt{focus on} targets, \texttt{workshop} remains the most frequent (20.0\%), followed by \texttt{inventory} (17.1\%) and \texttt{kitchen} (10.5\%), indicating a systematic object bias rather than random exploration. Figure~\ref{fig:death-timeline} visualizes the temporal pattern: agents execute long sequences of \texttt{connect} actions before a terminal \texttt{focus on} triggers death, typically in the final 1--3 steps.
623	
624	\begin{figure}[h]
625	\centering
626	\includegraphics[width=\columnwidth]{figures/death_action_distribution.pdf}
627	\caption{Action distribution for the internal (LLM) strategy in death ($n{=}105$) vs.\ non-death ($n{=}140$) episodes. Left: full distribution (both dominated by \texttt{connect}). Right: non-\texttt{connect} actions zoomed. \texttt{focus on} is moderately more frequent in death episodes ($5.4\%$ vs.\ $3.4\%$), while non-death episodes show higher rates of observation and object interaction.}
628	\label{fig:death-action-dist}
629	\end{figure}
630	
631	\begin{figure}[h]
632	\centering
633	\includegraphics[width=\columnwidth]{figures/death_action_timeline.pdf}
634	\caption{Step-by-step action sequences for 6 representative death episodes. The fatal \texttt{focus on} action (marked with arrow) consistently appears in the final steps after long \texttt{connect} sequences, and illustrates the ``connect loop $\to$ fatal focus'' pattern. Examples are drawn from the full 30-task dataset for task-type diversity; the pattern is identical in the 11-task analysis subset.}
635	\label{fig:death-timeline}
636	\end{figure}
637	
638	\begin{figure}[h]
639	\centering
640	\includegraphics[width=\columnwidth]{figures/death_action_comparison.pdf}
641	\caption{Non-\texttt{connect} action distribution comparison between internal (left) and deterministic (right) strategies. Within death episodes, both strategies exhibit comparable \texttt{focus on} rates (${\sim}5\%$); the internal strategy's higher death count (105 vs.\ 40) reflects more frequent entry into catastrophic states, not different action selection within those states.}
642	\label{fig:death-comparison}
643	\end{figure}
644	
645	\section{Grounding Ablation}
646	\label{app:grounding-ablation}
647	
648	We test whether directly intervening on the dominant death action (\texttt{focus on}) eliminates death vulnerability on the 10 death-prone tasks (baseline 48.0\%, $n{=}200$).
649	
650	\paragraph{Prompt warning.} Adding an explicit system prompt (``use \texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\% ($\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\texttt{identify-life-stages-1}: 35\%$\to$50\%; \texttt{identify-life-stages-2}: 25\%$\to$70\%), where explicit mention of the dangerous action may have increased its salience.
651	
652	\paragraph{Action-space filtering.} Blocking \texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\% ($\Delta = -19$~pp). The zero-passthrough rate suggests \texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.
653	
654	\paragraph{Per-task variation.} Under filtering, \texttt{identify-life-stages} and \texttt{inclined-plane} approach deterministic-level safety (${\sim}$15--20\% DR), while \texttt{chemistry-mix} and \texttt{find-animal} remain at 35--40\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \texttt{focus on} to incorrect objects.
655	
656	\section{Ablation Studies}
657	\label{app:ablations}
658	
659	\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\ref{tab:capacity}).
660	
661	\begin{table}[h]
662	\centering
663	\small
664	\begin{tabular}{@{}lcc@{}}
665	\toprule
666	Model & Step Bal.\ Acc.\ (\%) & Ep.\ Bal.\ Acc.\ (\%) \\
667	\midrule
668	Qwen3-0.6B & $56.4 \pm 3.5$ & $50.7 \pm 2.6$ \\
669	Qwen3-1.7B & $58.2 \pm 4.0$ & $43.1 \pm 1.0$ \\
670	Qwen3-4B & $59.2 \pm 3.5$ & $\mathbf{59.0 \pm 1.9}$ \\
671	\midrule
672	Always-det & 50.0 & 50.0 \\
673	\bottomrule
674	\end{tabular}
675	\caption{Capacity scaling: step-level and episode-level balanced accuracy (4 seeds, identical configuration across all scales). Step-level accuracy is flat ($56$--$59\%$, within seed variance). At episode level, only 4B breaks the random baseline ($59.0\%$, $p < 0.005$).}
676	\label{tab:capacity}
677	\end{table}
678	
679	Step-level balanced accuracy is flat across scales ($56$--$59\%$, within seed variance); step-level discrimination is not capacity-sensitive. At episode level, only 4B breaks the random baseline ($59.0 \pm 1.9\%$, $p < 0.005$); 0.6B and 1.7B remain at or below chance. The 1.7B model's below-chance episode-level accuracy ($43.1\%$) may reflect overfitting to spurious step-level correlations that anti-correlate with episode outcomes; without per-class confusion matrices at this scale, this remains a hypothesis. The dominant explanation across scales is that death avoidance constitutes a task-type-level binary signal that a step-level router cannot exploit efficiently.
680	
681	\paragraph{Generative router.} A generative routing model trained with explicit routing labels achieves balanced accuracy of 46.7\%, confirming that the routing bottleneck is signal-limited, not architecture-limited.
682	
683	\paragraph{Leave-one-task-type-out routing.} Under leave-one-task-type-out evaluation, blind routing collapses to always-deterministic (balanced accuracy 50.0\%); a keyword-based variant achieves 62.9\% only through task-identity leakage, not genuine routing signal. A guided router evaluated under the same protocol confirms this: without task-type identifiers it achieves chance accuracy (50.0\%), and leaking task names raises this to 62.9\%, confirming that the only learnable routing feature is task-type identity.
684	
685	\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\%, episode balanced accuracy 50.0\%, internal recall 0\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.
686	
687	\paragraph{Reasoning depth.} An ablation comparing chain-of-thought reasoning against direct-answer generation on 6 task types ($n{=}120$ episodes per condition, 6 tasks $\times$ 20 episodes per task) found no significant difference (Mann--Whitney $p > 0.26$, $|d| \leq 0.31$) and near-identical death rates (41.8\% vs.\ 42.5\%); reasoning depth does not meaningfully alter internal-mode outcomes.
688	
689	\section{Threshold Routing Analysis}
690	\label{sec:threshold-routing}
691	
692	Given per-task death risk knowledge, we test whether a simple threshold routing strategy can outperform always-deterministic. For each threshold $t \in [0, 1]$, we route to internal if the per-task internal death rate $\leq t$, otherwise to deterministic, and sweep all thresholds to find the optimal.
693	
694	\begin{table}[h]
695	\centering
696	\small
697	\resizebox{\columnwidth}{!}{%
698	\begin{tabular}{lccc}
699	\toprule
700	Strategy & Mean Score & Death Rate & $\Delta$ vs Det \\
701	\midrule
702	Always-det & $-9.47$ & $0.163$ & $0.00$ \\
703	Optimal threshold ($t{=}0$) & $-11.03$ & $0.155$ & $-1.56$ \\
704	Always-internal & $-39.07$ & $0.429$ & $-29.60$ \\
705	\bottomrule
706	\end{tabular}}
707	\caption{Death-risk threshold routing analysis on 245 episodes. The optimal threshold routes only \texttt{find-non-living-thing} (the sole zero-death task) to internal, with all other tasks routed to deterministic. Bootstrap 95\% CI for the difference: $[-8.87, +5.92]$.}
708	\label{tab:threshold-routing}
709	\end{table}
710	
711	Even with perfect per-task death risk knowledge, threshold routing cannot outperform always-deterministic. The sole zero-death task achieves higher scores under deterministic (+28.5) than internal (+18.9), leaving no room for a beneficial mixed strategy.
712	
713	\section{Practitioner Decision Framework}
714	\label{app:decision-framework}
715	
716	Given a new interactive environment, the following three-stage procedure diagnoses whether learned routing adds value over a fixed deterministic strategy.
717	
718	\paragraph{Stage 1: Pilot collection (${\sim}$50 episodes).}
719	Run pure-internal and pure-deterministic strategies on a representative sample (${\sim}$50 episode pairs). Compute the death-rate differential $\Delta\text{DR} = \text{DR}_{\text{int}} - \text{DR}_{\text{det}}$.
720	
721	\paragraph{Stage 2: Death dominance check.}
722	If $\Delta\text{DR} > 15$~pp, death asymmetry is likely the dominant routing signal. Compute the death-label fraction $f_{\text{death}}$: the proportion of non-tie routing labels where exactly one strategy dies.
723	
724	\paragraph{Stage 3: Decision.}
725	If $f_{\text{death}} > 75\%$, the routing signal is death-dominated; a fixed deterministic strategy will match or exceed any learned router. If $f_{\text{death}} < 50\%$, diverse routing signals may justify a learned router. Between 50\%--75\%, collect additional episodes to reduce estimation noise before committing to router development.
726	
727	\paragraph{Retrospective validation.}
728	All four experimental conditions in this paper are correctly classified:
729	
730	\begin{table}[h]
731	\centering
732	\small
733	\begin{tabular}{@{}lrrll@{}}
734	\toprule
735	Condition & $\Delta$DR & $f_{\text{death}}$ & Prediction & Actual \\
736	\midrule
737	Qwen-7B & +26.5 & 78.9\% & det-fixed & det wins \\
738	Llama-8B & +30.0 & $>$75\% & det-fixed & det wins \\
739	Qwen-72B & +27.8 & $>$75\% & det-fixed & det wins \\
740	MATH & +0.5 & 0\% & router viable & no signal \\
741	\bottomrule
742	\end{tabular}
743	\caption{Retrospective validation of the decision framework. All four conditions are correctly classified (4/4).}
744	\label{tab:decision-framework}
745	\end{table}
746	
747	The framework also predicts the inverted-U relationship between capability and death risk: below ${\sim}$0.5B parameters, agents rarely reach dangerous states (13.3\% death rate in a 15-episode pilot), so $\Delta\text{DR}$ is low and the framework would not recommend fixed-deterministic. Above ${\sim}$7B, agents are capable enough to enter catastrophic states but not capable enough to avoid them, producing high $\Delta\text{DR}$.
748	
749	\paragraph{Threshold calibration.} The thresholds above (15~pp, 75\%, 50\%) are illustrative, derived from ScienceWorld's specific reward structure (binary death penalty $P{=}100$, sparse terminal rewards). Environments with graded penalties, dense rewards, or qualitatively different failure modes may require different thresholds. Practitioners should calibrate these boundaries for their specific environment.
750	
751	\section{Extended Validation of Excluded Tasks}
752	\label{app:extended-validation}
753	
754	To verify that task exclusion does not bias toward death-prone tasks, we collect $n{=}20$ episodes for five representative excluded tasks spanning all exclusion categories (Table~\ref{tab:extended-val}).
755	
756	\begin{table}[h]
757	\centering
758	\small
759	\resizebox{\columnwidth}{!}{%
760	\begin{tabular}{lcrrrrc}
761	\toprule
762	Task & Category & $n$ & Int DR & Det DR & $\Delta$DR & D/I/N \\
763	\midrule
764	boil & dev-set & 20 & 55\% & 25\% & +30\,pp & 6/0/14 \\
765	melt & dev-set & 20 & 45\% & 20\% & +25\,pp & 7/2/11 \\
766	find-living-thing & taxonomic & 20 & 55\% & 15\% & +40\,pp & 10/0/10 \\
767	use-thermometer & agent-floor & 20 & 50\% & 20\% & +30\,pp & 7/1/12 \\
768	power-component & agent-floor & 20 & 50\% & 15\% & +35\,pp & 7/0/13 \\
769	\midrule
770	\textit{Mean (5 tasks)} & & 100 & 51.0\% & 19.0\% & +32.0\,pp & 37/3/60 \\
771	\bottomrule
772	\end{tabular}}
773	\caption{Extended validation ($n{=}20$) of representative excluded task types. All five tasks confirm death asymmetry; mean $\Delta$DR $= +32.0$\,pp is consistent with the $n{=}5$ prescreening estimate for these same tasks (Table~\ref{tab:excluded-death}).}
774	\label{tab:extended-val}
775	\end{table}
776	
777	Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\ref{tab:per-task}), indicating that excluded tasks are \emph{more} death-dominated than included tasks---the opposite of a cherry-picking bias.
778	
779	\section{Agent Prompt Templates}
780	\label{app:prompt-templates}
781	
782	Below we show the complete prompt templates used for agent interaction in ScienceWorld. Both the internal (ReAct) and deterministic strategies share the same system prompt but differ in the user message template.
783	
784	\paragraph{System prompt (shared).} Used for all ScienceWorld agent interactions across both computation modes.
785	
786	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
787	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
788	  left=2mm, right=2mm, top=1mm, bottom=1mm}
789	You are an agent interacting with a ScienceWorld text
790	environment. Your goal is to complete the given task by
791	choosing actions from the available action list.
792	
793	Use the following format for each step:
794	Thought: &lt;your reasoning about what to do next>
795	Action: &lt;exact action string from the valid actions list>
796	
797	Rules:
798	- You MUST choose an action from the valid actions list.
799	  Do not invent actions.
800	- Think step by step about what physical/scientific
801	  process is needed.
802	- Pay attention to the current observation for clues
803	  about object states.
804	\end{tcblisting}
805	
806	\paragraph{Internal (ReAct) user template.} At each step, the agent receives the current observation, valid action list, and recent action history, and must select a single action.
807	
808	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
809	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
810	  left=2mm, right=2mm, top=1mm, bottom=1mm}
811	Current observation:
812	{observation}
813	
814	Valid actions:
815	{valid_actions_str}
816	
817	Previous actions taken: {history_str}
818	
819	Choose your next action.
820	\end{tcblisting}
821	
822	\paragraph{Deterministic candidate generation template.} For the deterministic strategy, the agent generates ranked candidate actions instead of selecting one; these candidates are then evaluated via simulator forking (\S\ref{sec:method}).
823	
824	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
825	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
826	  left=2mm, right=2mm, top=1mm, bottom=1mm}
827	Current observation:
828	{observation}
829	
830	Valid actions:
831	{valid_actions_str}
832	
833	Previous actions taken: {history_str}
834	
835	Generate the top 3 most promising actions from the valid
836	actions list, ranked by how likely they are to make
837	progress on the task. Output exactly 3 actions, one per
838	line, in this format:
839	1. &lt;action>
840	2. &lt;action>
841	3. &lt;action>
842	\end{tcblisting}
843	
844	\paragraph{Reflexion self-reflection prompt.} After a failed episode, the Reflexion agent (\S\ref{sec:agent-improvement}) generates a reflection that is injected into subsequent trial attempts as additional system context.
845	
846	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
847	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
848	  left=2mm, right=2mm, top=1mm, bottom=1mm}
849	You just completed an episode in a ScienceWorld text
850	environment but failed.
851	
852	Task: {task_name}
853	Final score: {final_score}
854	Outcome: {outcome}
855	Number of steps taken: {num_steps}
856	
857	Here is a summary of your actions:
858	{action_summary}
859	
860	Analyze why this episode failed and provide a short
861	strategy for the next attempt. Focus on:
862	1. What went wrong (wrong sequence, missed key step,
863	   dangerous action)?
864	2. What should be done differently next time?
865	
866	Keep your reflection under 200 words.
867	\end{tcblisting}
868	
869	\paragraph{Grounding warning (ablation).} The prompt warning condition in the grounding ablation (Appendix~\ref{app:grounding-ablation}) appends the following to the shared system prompt:
870	
871	\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,
872	  listing options={basicstyle=\small\ttfamily,breaklines=true,columns=fullflexible},
873	  left=2mm, right=2mm, top=1mm, bottom=1mm}
874	CRITICAL SAFETY RULE: The 'focus on [object]' action is
875	ONLY for submitting your final answer. Do NOT use
876	'focus on' to examine, inspect, or interact with objects
877	during exploration. Using 'focus on' on the wrong object
878	will cause irreversible failure. Use 'look at',
879	'examine', or 'pick up' instead for exploration.
880	\end{tcblisting}
881	
882	\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \emph{select} one action (ReAct), while the deterministic strategy asks it to \emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.
883	
884	\input{responsibleNLPchecklist}
885	
886	\end{document}
887	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0585d0b5-af02-4841-b6e5-290de6e709de",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "c9a9e593-853f-44a1-a2e3-19716cae8a1a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\n\\usepackage[review]{acl}\n\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{graphicx}\n\\graphicspath{{figures/}}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{algorithm}\n\\usepackage{algorithmic}\n\\usepackage{tcolorbox}\n\\tcbuselibrary{listings,breakable}\n\n\\hypersetup{pdfauthor={},pdftitle={}}\n\n\\title{Death Avoidance as the Dominant Routing Signal:\\\\A Counterfactual Analysis on ScienceWorld}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\\input{introduction}\n\\input{method}\n\\input{experiments}\n\\input{related_work}\n\\input{discussion}\n\\input{conclusion}\n\n\\section*{Limitations}\n\n\\paragraph{Environmental scope.}\nOur primary analysis uses a single environment (ScienceWorld, 11 of 30 task types) with one backbone (Qwen2.5-7B-Instruct), though extended validation of representative excluded tasks confirms the pattern (Appendix~\\ref{app:extended-validation}). The $-100$ death penalty amplifies DAF; environments with softer penalties would exhibit lower DAF values (Appendix~\\ref{app:penalty}). The 19 excluded task types (63\\%) lack routing signal because both strategies typically time out within 30 steps; increasing the step budget could surface non-death-dominated signal that our current setup does not capture. Cross-environment analyses on MATH and ALFWorld (\\S\\ref{sec:cross-env}, \\S\\ref{sec:discussion}) provide preliminary supporting evidence but do not conclusively establish generalization. A Llama-3.1-8B-Instruct cross-model replication (11 task types, $N{=}220$; \\S\\ref{sec:cross-model}) shows death dominance replicates with direction consistency 10/10 while vulnerability magnitude varies ($+30.0$~pp vs.\\ Qwen $+26.5$~pp), though both models are in the 7--8B parameter range; Qwen2.5-72B ($10{\\times}$ scale) reduces death rate but does not eliminate death dominance (\\S\\ref{sec:agent-improvement}); validation beyond 72B remains future work. Our quantitative results (DAF $= 90.4\\%$, label fractions) are specific to ScienceWorld; the framework's generality claim is methodological (the diagnostic procedure applies to any environment with asymmetric fatal outcomes), not empirical (the specific percentages may differ across environments).\n\n\\paragraph{Methodological constraints.}\nOur internal-reasoning baseline uses single-pass ReAct~\\citep{react-2023}. Reflexion~\\citep{reflexion-2023} reduces death rate from 42.9\\% to 31.4\\% (\\S\\ref{sec:agent-improvement}), but more aggressive self-correction or Tree-of-Thought backtracking~\\citep{tot-2023} may further reduce internal death rates. Episode-level labels assign a single routing preference to entire episodes, which may be suboptimal for individual steps (particularly those preceding death events). However, of 2{,}040 training steps only 0.3\\% exhibit strict directional conflict (step-level oracle opposite to episode label); the remaining apparent mislabeling consists of episode labels applied to steps where neither strategy has a step-level advantage (60.3\\% pre-event neutral). The issue is granularity mismatch---applying correct-direction labels to uninformative steps---not directional error. Training on pure-strategy trajectories also introduces distribution shift at deployment~\\citep{dagger-2011}. Under mixed-strategy routing with oracle death prediction, switching to deterministic at the step before death could reduce the internal death rate; even under optimistic assumptions (perfect step-level death prediction), a residual gap of ${>}10$~pp between strategies is expected, as fatal trajectories involve cumulative hallucination errors preceding the death event. More broadly, projecting episode-level labels onto 10--50 sequential steps with path-dependent state introduces compounding error: early routing decisions alter the state trajectory, potentially invalidating later labels derived from the episode outcome.\n\n\\paragraph{Statistical limitations.}\nEpisodes within the same task type are not fully independent because they share environment dynamics, though they use different random seeds. Cluster bootstrap with $K{=}11$ task-type clusters yields wider CIs ($[73.3\\%, 100.0\\%]$); with $K < 40$ clusters, these should be interpreted cautiously~\\citep{cameron-2008,webb-2023}. A wild cluster bootstrap ($K{=}11$, $p < 0.001$; Appendix~\\ref{app:wild-cluster}) and 100\\% directional consistency across all 28 death-prone tasks (Appendix~\\ref{app:per-task-ci}) mitigate this concern.\n\n\\paragraph{Pure-strategy upper bound.}\nOur counterfactual analysis compares pure strategies (always-internal vs.\\ always-deterministic). In mixed routing, the router can selectively invoke deterministic mode on high-risk steps, potentially reducing death asymmetry. Thus, DAF${=}90.4\\%$ represents an upper bound on death avoidance's contribution to optimized routing; the actual contribution under mixed strategies may be lower.\n\n\\paragraph{Diagnostic scope.}\nOur framework is diagnostic rather than prescriptive: it identifies what drives routing decisions but does not optimize the routing policy itself. Extending the counterfactual decomposition to prescribe optimal mixed-strategy routing---for example, by combining DAF analysis with online policy learning---is a natural next step.\n\n\\section*{Ethics Statement}\n\nThis work uses ScienceWorld \\citep{scienceworld-2022}, a publicly available text-based simulation environment, and does not involve human subjects or private data. All evaluation environments (ScienceWorld, ALFWorld, MATH) are released under permissive open-source licenses (Apache 2.0 / MIT). All models used (Qwen2.5 family, Llama-3.1-8B, Gemma-2-9B-it) are publicly available for research use. All language models are accessed via standard APIs or publicly released weights. Experiments were conducted on 2$\\times$ NVIDIA RTX 5090 (32GB) and 4$\\times$ NVIDIA RTX 6000 PRO (96GB), totaling approximately 200 GPU-hours, comprising ${\\sim}$140 hours for episode collection (counterfactual inference across three 7--9B model families plus Qwen2.5-72B backbone scaling, Reflexion and retry baselines, and cross-environment validation on ALFWorld and MATH), ${\\sim}$35 hours for router training (LoRA fine-tuning of Qwen3-0.6B/1.7B/4B across 4--8 seeds per scale, including augmentation and ablation variants), and ${\\sim}$25 hours for evaluation and analysis. Code and data will be released upon acceptance.\n\n\\bibliography{references}\n\n\\appendix\n\n\\noindent\\textbf{Appendix Overview.}\n\\hyperref[app:sci]{A.~Signal Concentration Index} $\\cdot$\n\\hyperref[app:labeling]{B.~Labeling Quality Audit} $\\cdot$\n\\hyperref[app:per-task]{C.~Per-Task Decomposition} $\\cdot$\n\\hyperref[app:correlation]{D.~Correlation Robustness} $\\cdot$\n\\hyperref[app:wild-cluster]{E.~Cluster Bootstrap Sensitivity} $\\cdot$\n\\hyperref[app:per-task-ci]{F.~Per-Task CIs} $\\cdot$\n\\hyperref[app:loto-daf]{G.~Leave-One-Task-Out DAF} $\\cdot$\n\\hyperref[app:dose-response]{H.~Dose-Response Breakdown} $\\cdot$\n\\hyperref[app:router-details]{I.~Router Training Details} $\\cdot$\n\\hyperref[app:seed-robustness]{J.~Seed Robustness} $\\cdot$\n\\hyperref[app:penalty]{K.~Penalty Sensitivity} $\\cdot$\n\\hyperref[app:cross-env-details]{L.~Cross-Environment Details} $\\cdot$\n\\hyperref[app:cross-model]{M.~Cross-Model Verification} $\\cdot$\n\\hyperref[app:failure-modes]{N.~Failure Mode Analysis} $\\cdot$\n\\hyperref[app:grounding-ablation]{O.~Grounding Ablation} $\\cdot$\n\\hyperref[app:ablations]{P.~Ablation Studies} $\\cdot$\n\\hyperref[sec:threshold-routing]{Q.~Threshold Routing} $\\cdot$\n\\hyperref[app:decision-framework]{R.~Decision Framework} $\\cdot$\n\\hyperref[app:extended-validation]{S.~Extended Validation} $\\cdot$\n\\hyperref[app:prompt-templates]{T.~Agent Prompt Templates}\n\n\\section{Signal Concentration Index}\n\\label{app:sci}\n\nLet $K$ denote the number of task types and $c_k$ the contribution of task type $k$ to the aggregate routing signal, defined as the fraction of total death-rate differential attributable to task $k$:\n\\begin{equation}\n    c_k = \\frac{n_k \\cdot \\delta_k}{\\sum_{j=1}^{K} n_j \\cdot \\delta_j}\n\\end{equation}\nwhere $n_k$ is the number of episodes and $\\delta_k = d_k^{\\tt int} - d_k^{\\tt det}$ is the per-task death-rate differential. The SCI is the Gini coefficient over $\\{c_1, \\ldots, c_K\\}$:\n\\begin{equation}\n    \\text{SCI} = \\frac{\\sum_{i=1}^K \\sum_{j=1}^K |c_i - c_j|}{2K \\sum_{k=1}^K c_k}\n\\end{equation}\n\n\\section{Labeling Quality Audit}\n\\label{app:labeling}\n\n\\begin{algorithm}[t]\n\\caption{Episode-Level Counterfactual Labeling}\n\\label{alg:labeling}\n\\begin{algorithmic}[1]\n\\REQUIRE Task instance $t$, computation modes $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$\n\\ENSURE Label $\\ell \\in \\{{\\tt det\\text{-}pref}, {\\tt int\\text{-}pref}, {\\tt no\\text{-}pref}\\}$\n\\FOR{each $m \\in \\mathcal{M}$}\n    \\STATE Run episode $\\tau_m$ with pure-strategy $m$\n    \\STATE Record score $s_m$ and death indicator $d_m$\n\\ENDFOR\n\\IF{$d_{\\tt int} = 1$ \\AND $d_{\\tt det} = 0$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = 0$ \\AND $d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{both dead}\n\\ELSIF{$s_{\\tt det} > s_{\\tt int}$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSIF{$s_{\\tt int} > s_{\\tt det}$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSE\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{tied alive}\n\\ENDIF\n\\RETURN $\\ell$\n\\end{algorithmic}\n\\end{algorithm}\n\nNote that episode-level labels are used to evaluate step-level predictions, introducing a granularity mismatch rather than independent validation. A potential concern is oracle circularity: whether episode-level labels reflect tie-breaking artifacts rather than genuine computation mode differences. We audit all 245 labels. Of the 150 \\texttt{no\\_preference} labels (61.2\\%), 115 (46.9\\%) are both-alive ties and 35 (14.3\\%) are both-dead, all excluded from router training. The remaining 95 training labels are entirely genuine: 75 from death asymmetry (70 deterministic-preferred, 5 internal-preferred) and 20 from score comparison with both strategies surviving (16 deterministic-preferred, 4 internal-preferred). Zero labels depend on tie-breaking. Retraining the router using only death-asymmetry labels yields step-level balanced accuracy of 57.3\\%, within 1$\\sigma$ of the full-label retrain (57.6 $\\pm$ 0.5\\%, step-level Trainer evaluation); score-comparison labels contribute negligible additional signal. (Step-level metrics are used here for the relative comparison; as shown in \\S\\ref{sec:router-diagnostic}, absolute generalization to new episodes is near chance.) The 97.4\\% step-level tie rate (\\S\\ref{sec:collection}) further motivates episode-level over step-level labeling.\n\n\\section{Per-Task Decomposition}\n\\label{app:per-task}\nWe use ScienceWorld v1.2.3~\\citep{scienceworld-2022}.\nWe select 11 of ScienceWorld's 30 task types for analysis. Types are excluded when they were used for pipeline development (5 tasks, standard hold-out practice), are taxonomically redundant with a retained family representative (7 tasks), or exhibit near-zero task progress under both strategies (7 tasks, agent capability floor).\\footnote{Excluded tasks exhibit even stronger death dominance than included tasks ($\\Delta\\text{DR} = +38.2$\\,pp vs.\\ $+28.7$\\,pp; Table~\\ref{tab:excluded-death}).}\n\n\\begin{table}[h]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2.5pt}\n\\begin{tabular}{@{}lrrccc@{}}\n\\toprule\nTask & $n$ & $\\Delta_\\text{full}$ & D\\%\\textsubscript{int} & D\\%\\textsubscript{det} & D / I / N \\\\\n\\midrule\nid-life-stages-1       & 20  & $+47.50$ & 55   & 10   & 9 / 0 / 11  \\\\\nlifespan-long          & 25  & $+44.00$ & 56   & 16   & 11 / 1 / 13 \\\\\nlifespan-l-then-s      & 20  & $+40.80$ & 45   & 10   & 8 / 1 / 11  \\\\\ninclined-plane         & 20  & $+36.00$ & 55   & 20   & 7 / 0 / 13  \\\\\nfreeze                 & 20  & $+30.50$ & 55   & 25   & 6 / 0 / 14  \\\\\nmeas-melt-point        & 20  & $+30.05$ & 55   & 25   & 6 / 0 / 14  \\\\\nid-life-stages-2       & 20  & $+30.00$ & 50   & 20   & 6 / 0 / 14  \\\\\nfind-animal            & 20  & $+26.65$ & 50   & 25   & 5 / 0 / 15  \\\\\ngrow-fruit             & 20  & $+25.10$ & 45   & 20   & 6 / 1 / 13  \\\\\nchem-mix               & 20  & $+21.80$ & 45   & 25   & 6 / 2 / 12  \\\\\n\\midrule\nfind-non-living-thing$^\\dagger$ & 40 & $+9.58$ & 0  & 0    & 16 / 4 / 20 \\\\\n\\midrule\n\\textbf{All (11 tasks)} & \\textbf{245} & $\\mathbf{+29.60}$ & \\textbf{42.9} & \\textbf{16.3} & \\textbf{86 / 9 / 150} \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-task decomposition of the death avoidance effect. D\\%: death rate for internal (int) and deterministic (det) strategies. D/I/N: episode labels (det-preferred / internal-preferred / no-preference). Sorted by $\\Delta_{\\text{full}}$ descending. The \\textit{All} row is an episode-weighted aggregate across 245 episodes. $\\dagger$\\,Only task with zero deaths under both strategies; $n{=}40$ because data was collected in two batches, with the second batch adding 20 episodes to increase statistical power for this zero-death outlier.}\n\\label{tab:per-task}\n\\end{table}\n\n\\paragraph{Task selection and anti-cherry-picking.}\nEighteen of the 19 excluded task types (95\\%) exhibit death-asymmetric patterns (Table~\\ref{tab:excluded-death}): internal-reasoning death rates range from 40\\% to 60\\% (mean 53.9\\%), while deterministic death rates range from 0\\% to 40\\% (mean 15.8\\%), yielding a mean death-rate differential of $+38.2$\\,pp, exceeding the $+28.7$\\,pp for included tasks. The included subset is thus \\emph{less} death-asymmetric than the excluded subset, the opposite of what a cherry-picking hypothesis would predict. The sole exception is \\texttt{grow-plant}, an intrinsically safe task with zero deaths under both strategies, paralleling \\texttt{find-non-living-thing} in the included set. The 19 excluded tasks fall into three independently motivated categories: five used during pipeline development (standard hold-out practice), seven taxonomically redundant with included family representatives (deduplication), and seven where the 7B backbone achieves near-zero task progress regardless of strategy (agent capability floor). In no case was a task excluded because death dominance was absent. Exclusion is driven by absence of non-death routing signal ($\\Delta_{\\text{nd}} = 0$ for 53\\% of excluded tasks) and standard deduplication practices. \\texttt{find-non-living-thing} serves as an internal counterexample: zero deaths under both strategies yet included because it exhibits non-death routing signal ($\\Delta_{\\text{full}} = +9.58$ entirely from score differences), and deterministic is not always preferred (4 of 20 non-tie labels favor internal).\n\n\\begin{table}[t]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2pt}\n\\begin{tabular}{@{}llrcccl@{}}\n\\toprule\nTask & Grp & $n$ & D\\%\\textsubscript{int} & D\\%\\textsubscript{det} & $\\Delta$DR & Excl.\\ reason \\\\\n\\midrule\nboil                          & A & 20 & 50 & 20 & $+30$ & dev set \\\\\nchange-state-of-matter        & A & 20 & 55 & 15 & $+40$ & dev set \\\\\nchem-mix-paint-secondary      & A & 20 & 45 & 10 & $+35$ & dev set \\\\\ngrow-plant                    & A & 20 &  0 &  0 & $\\phantom{+}0$  & dev set \\\\\nmelt                          & A & 20 & 55 & 15 & $+40$ & dev set \\\\\n\\midrule\nchem-mix-paint-tertiary       & B &  5 & 40 & 20 & $+20$ & family redundancy \\\\\nfind-living-thing             & B &  5 & 60 & 20 & $+40$ & family redundancy \\\\\nfind-plant                    & B &  5 & 60 &  0 & $+60$ & family redundancy \\\\\ninclined-friction-named       & B &  5 & 60 & 20 & $+40$ & family redundancy \\\\\ninclined-friction-unnamed     & B &  5 & 60 &  0 & $+60$ & family redundancy \\\\\nlifespan-shortest             & B &  5 & 60 & 40 & $+20$ & family redundancy \\\\\nmeasure-melt-known            & B &  5 & 60 &  0 & $+60$ & family redundancy \\\\\n\\midrule\nmendelian-known               & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\nmendelian-unknown             & C &  5 & 60 & 40 & $+20$ & agent floor \\\\\npower-component               & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\npower-renewable               & C &  5 & 60 &  0 & $+60$ & agent floor \\\\\ntest-conductivity             & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\ntest-conductivity-unknown     & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\nuse-thermometer               & C &  5 & 60 & 20 & $+40$ & agent floor \\\\\n\\midrule\n\\textbf{Mean (19 excluded)}   &   &    & \\textbf{53.9} & \\textbf{15.8} & $\\mathbf{+38.2}$ & \\\\\n\\textit{cf.\\ included (11)}   &   &    & \\textit{46.5} & \\textit{17.8} & $\\textit{+28.7}$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Death-rate analysis of all 19 excluded task types. D\\%: death rate (score $\\leq -100$). $\\Delta$DR = D\\%\\textsubscript{int} $-$ D\\%\\textsubscript{det}. 18 of 19 excluded tasks (95\\%) exhibit positive death asymmetry ($\\Delta$DR $\\geq +20$\\,pp). Exclusion groups: A = development set (excluded to prevent circular evaluation), B = taxonomically redundant with an included family representative, C = agent-floor tasks (backbone achieves near-zero progress regardless of strategy). The mean $\\Delta$DR among excluded tasks ($+38.2$\\,pp) exceeds that of included tasks ($+28.7$\\,pp), confirming that task selection does not bias toward death-prone tasks. Group B--C estimates are based on $n{=}5$ prescreening episodes per task and should be interpreted as directional evidence rather than precise rate estimates.}\n\\label{tab:excluded-death}\n\\end{table}\n\n\\section{Correlation Robustness}\n\\label{app:correlation}\n\nThe Pearson $r = 0.9698$ reported in \\S\\ref{sec:death-decomp} is robust across multiple diagnostics. Spearman rank correlation is $\\rho = 0.986$ ($p = 2.4 \\times 10^{-8}$); the relationship is not driven by outliers or non-linearity. A nonparametric bootstrap (10{,}000 resamples) yields 95\\% CI $[0.952, 0.995]$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lr@{}}\n\\toprule\nTask removed & $r_{\\text{LOO}}$ \\\\\n\\midrule\nid-life-stages-1       & 0.963 \\\\\nlifespan-long          & 0.969 \\\\\nlifespan-l-then-s      & 0.976 \\\\\ninclined-plane         & 0.969 \\\\\nfreeze                 & 0.971 \\\\\nmeas-melt-point        & 0.972 \\\\\nid-life-stages-2       & 0.972 \\\\\nfind-animal            & 0.970 \\\\\ngrow-fruit             & 0.973 \\\\\nchem-mix               & 0.969 \\\\\nfind-non-living-thing  & 0.980 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\\ $\\Delta_{\\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}\n\\label{tab:loo}\n\\end{table}\n\n\\section{Cluster Bootstrap Sensitivity Analysis}\n\\label{app:wild-cluster}\n\nWith $K{=}11$ task-type clusters, cluster bootstrap falls well below the $K{\\geq}20$--30 recommended for reliable inference \\citep{cameron-2008,webb-2023}. The narrower CIs obtained reflect known small-sample bias toward underestimation of variance, not tighter inference.\n\nEpisodes within the same task type share environment dynamics, raising the concern that the effective sample size is closer to $K$ (task types) than $N$ (episodes). We address this with cluster-robust inference treating each task type as a cluster ($K{=}11$, all 11 included task types, 245 episodes).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nMethod & $p$-value & 95\\% CI \\\\\n\\midrule\nCluster-robust $t$-test ($t{=}10.0$, df$=$10) & $< 0.001$ & $[0.73, 1.00]$ \\\\\nWild cluster bootstrap ($B{=}9{,}999$) & $< 0.001$ & $[0.73, 1.00]$ \\\\\nExact permutation ($2{,}048$ perms) & $0.002$ & --- \\\\\nSign test & $< 0.001$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Cluster-level tests of death-rate asymmetry ($K{=}11$ task clusters, 245 episodes). 10 of 11 clusters show internal DR $>$ deterministic DR; the sole exception (\\texttt{find-non-living-thing}) has zero deaths under both strategies. Cohen's $d = 3.02$. The exact permutation $p = 0.002$ ($4/2{,}048$) reflects the near-unanimous directional consistency.}\n\\label{tab:wild-cluster}\n\\end{table}\n\n\\noindent All methods confirm significance with $p < 0.01$, and the 95\\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.\n\nWe retain this analysis for transparency; readers should rely on the non-clustered episode-level bootstrap (\\S\\ref{sec:death-decomp}) as the primary inference.\n\n\\section{Per-Task Death Rate Confidence Intervals}\n\\label{app:per-task-ci}\n\nWe compute bootstrap 95\\% CIs for the death-rate differential ($\\Delta\\text{DR} = \\text{DR}_{\\text{int}} - \\text{DR}_{\\text{det}}$) for all 30 ScienceWorld task types. Of 30 tasks, 28 are death-prone (at least one death under either strategy); the remaining 2 (\\texttt{grow-plant}, \\texttt{find-non-living-thing}) have zero deaths under both strategies.\n\nAcross all 28 death-prone tasks, internal DR exceeds deterministic DR without exception (100\\% directional consistency). The pooled death-rate differential is $+37.3\\%$ (95\\% CI: $[29.7\\%, 44.4\\%]$). Fifteen of 28 tasks are individually significant (CI excludes zero); the 13 non-significant tasks all have $n{=}5$ prescreening episodes, where statistical power is insufficient to detect even large effects (e.g., a task with $\\Delta\\text{DR} = +40$\\,pp at $n{=}5$ has a CI of $\\pm 43$\\,pp). The universal directional consistency, combined with the pooled significance, confirms that death asymmetry is not driven by a subset of outlier tasks.\n\n\\section{Leave-One-Task-Out DAF Sensitivity}\n\\label{app:loto-daf}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Leave-one-task-out DAF sensitivity (penalty-independent label fraction). Among the 10 death-prone tasks, removing any single task changes DAF by at most 3.0\\,pp (range: 75.9\\%--78.9\\%). Removing \\emph{Find Non-Living Thing}, the sole death-free task that contributes all 20 score-comparison episodes, raises DAF to 100\\% by construction.}\n\\label{tab:loto-daf}\n\\begin{tabular}{lrrr}\n\\toprule\nRemoved Task & $N_\\text{rem}$ & DAF (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\n(none, full) & 245 & 78.9 & --- \\\\\n\\midrule\nFind Non-Living$^\\dagger$ & 205 & 100.0 & +21.1 \\\\\nLifespan Longest & 220 & 75.9 & $-$3.0 \\\\\nLife Stages 1 & 225 & 76.7 & $-$2.2 \\\\\nLifespan Long+Short & 225 & 76.7 & $-$2.2 \\\\\nChemistry Mix & 225 & 77.0 & $-$1.9 \\\\\nGrow Fruit & 225 & 77.3 & $-$1.7 \\\\\nInclined Plane Angle & 225 & 77.3 & $-$1.7 \\\\\nFreeze & 225 & 77.5 & $-$1.4 \\\\\nLife Stages 2 & 225 & 77.5 & $-$1.4 \\\\\nMelt Pt Unknown & 225 & 77.5 & $-$1.4 \\\\\nFind Animal & 225 & 77.8 & $-$1.2 \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{2pt}\n{\\footnotesize $^\\dagger$Only death-free task; contributes all score-comparison labels. Sorted by $|\\Delta|$ descending.}\n\\end{table}\n\n\\section{Per-Task Dose-Response Breakdown}\n\\label{app:dose-response}\n\nTable~\\ref{tab:dose-response-detail} reports per-task death rates for Reflexion at $N{=}3$, 4, and 5 on the 10 death-prone tasks ($n{=}20$ episodes per task). Per-task variance is high (up to 25\\,pp range for \\texttt{measure-melting-point}), but the aggregate smooths to a 2.5\\,pp band, confirming that the stabilization conclusion is robust at the aggregate level despite task-level noise. \\texttt{freeze} is consistently the hardest task (50--60\\% DR across all $N$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-task death rates (\\%) for Reflexion at $N{=}3$, 4, 5 on 10 death-prone tasks ($n{=}20$ per task). Aggregate death rates confirm stabilization at $N \\geq 3$ (range: $34.0$--$36.5\\%$).}\n\\label{tab:dose-response-detail}\n\\begin{tabular}{@{}lrrr@{}}\n\\toprule\nTask & $N{=}3$ & $N{=}4$ & $N{=}5$ \\\\\n\\midrule\nchemistry-mix & 25.0 & 35.0 & 20.0 \\\\\nfind-animal & 45.0 & 30.0 & 45.0 \\\\\nfreeze & 50.0 & 50.0 & 60.0 \\\\\ngrow-fruit & 30.0 & 25.0 & 25.0 \\\\\nidentify-life-stages-1 & 35.0 & 35.0 & 35.0 \\\\\nidentify-life-stages-2 & 25.0 & 25.0 & 30.0 \\\\\ninclined-plane-angle & 20.0 & 30.0 & 35.0 \\\\\nlifespan-longest & 45.0 & 40.0 & 40.0 \\\\\nlifespan-long+short & 30.0 & 45.0 & 35.0 \\\\\nmeasure-melting-pt & 35.0 & 50.0 & 25.0 \\\\\n\\midrule\n\\textbf{Aggregate} & \\textbf{34.0} & \\textbf{36.5} & \\textbf{35.0} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Router Training Details}\n\\label{app:router-details}\n\nWe use Qwen3-1.7B for the router to avoid circular dependency with the Qwen2.5-7B data-generating model.\n\nWith gradient accumulation of 1 (effective batch size 4), routing performance is highly sensitive to the evaluation split; this suggests overfitting to specific train/validation partition boundaries. With gradient accumulation of 8 (effective batch size 32), step-level performance stabilizes across splits (${\\sim}54\\%$ balanced accuracy). All reported results use gradient accumulation 8.\n\nUnder step-level evaluation with a fixed data split, cross-seed balanced accuracy ranges from 52.7\\% to 58.1\\%, but internal recall varies from 51.5\\% to 81.8\\%, which reflects threshold sensitivity. However, episode-level evaluation reveals that this apparent discrimination does not generalize: balanced accuracy drops to $47.1 \\pm 2.2\\%$ across 8 cross-split seeds (Appendix~\\ref{app:seed-robustness}). Deployed end-to-end, the trained router allocates 97.0\\% of episodes to deterministic computation with 17.6\\% death rate, and misrouting cost (death from internally-routed episodes) exceeds the benefit of correctly routing rare internal-preferred cases.\n\n\\paragraph{Evaluation methods.} All results use \\emph{generation-based evaluation}: the model generates a routing label as text (\\texttt{enable\\_thinking=False}), parsed for classification. We evaluate at two granularities: \\emph{step-level} (steps from the same episode may appear in both train and validation sets) and \\emph{episode-level} (entire episodes held out). Step-level accuracy ($54.1 \\pm 5.4\\%$) exceeds chance (the router captures some signal), but episode-level accuracy ($47.1 \\pm 2.2\\%$, below chance) shows this does not generalize to unseen episodes. Paraphrase-based text augmentation (Appendix~\\ref{app:seed-robustness}) provides no improvement; real-data scaling remains open. Always-deterministic is trivially near-optimal given DAF $= 90.4\\%$. The main text (\\S\\ref{sec:router-diagnostic}) reports controlled 4-seed results at three scales; the model-size ablation (Appendix~\\ref{app:ablations}) provides further detail.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nHyperparameter & Classification Head & Implicit Router \\\\\n\\midrule\nBase model & Qwen3-1.7B & Qwen3-1.7B \\\\\nArchitecture & Linear + LoRA & SFT + LoRA \\\\\nLoRA $r$ / $\\alpha$ & 16 / 32 & 16 / 32 \\\\\nLearning rate & 2e-5 & 2e-4 \\\\\nOptimizer & AdamW & AdamW \\\\\nEpochs & 3 & 3 \\\\\nBatch size (per device) & 4 & 4 \\\\\nGradient accumulation & 8 & 8 \\\\\nWarmup ratio & 0.1 & 0.1 \\\\\nWeight decay & 0.01 & 0.01 \\\\\nMax sequence length & 512 & 512 \\\\\nSeeds & \\{42\\} & \\{42, 123, 456, 789\\} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Router training hyperparameters. Both architectures use the same base model with LoRA adaptation. The classification head degenerates across all configurations; the implicit router results are reported as 4-seed mean$\\pm$std.}\n\\label{tab:hyperparams}\n\\end{table}\n\n\\paragraph{Agent inference parameters.}\nFor ScienceWorld, each agent step uses temperature $T{=}0.3$ and maximum generation length of 256 tokens, served via vLLM v0.21.0. Top-$p$ is left at the vLLM default of $1.0$ (no nucleus sampling). For MATH, the agent uses greedy decoding ($T{=}0.0$) with a maximum of 2{,}048 tokens per generation. For ALFWorld, we use $T{=}0.3$ with 256 maximum tokens. All three environments use Qwen2.5-7B-Instruct~\\citep{qwen25-2024} as the backbone.\n\n\\section{Seed Robustness}\n\\label{app:seed-robustness}\n\nWe assess router generalization at two evaluation granularities: \\emph{step-level}, where steps from the same episode may appear in both train and validation sets, and \\emph{episode-level}, where entire episodes are held out. Both use cross-split evaluation (seeds $\\{42, \\ldots, 49\\}$, 8 seeds total), where the data partition and training seed both vary. Table~\\ref{tab:seed-robustness} reports per-seed results.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}llcc@{}}\n\\toprule\nEval.\\ Granularity & Seed & Bal.\\ Acc.\\ (\\%) \\\\\n\\midrule\nStep-level & 42 & 57.06 \\\\\n(same-episode & 43 & 63.99 \\\\\nleakage) & 44 & 55.43 \\\\\n & 45 & 56.14 \\\\\n & 46 & 55.45 \\\\\n & 47 & 50.08 \\\\\n & 48 & 48.03 \\\\\n & 49 & 59.30 \\\\\n\\cmidrule{2-3}\n & Mean$\\pm$std & $54.1 \\pm 5.4$ \\\\\n\\midrule\nEpisode-level & 42 & 48.1 \\\\\n(held-out & 43 & 47.9 \\\\\nepisodes) & 44 & 49.6 \\\\\n & 45 & 49.4 \\\\\n & 46 & 48.5 \\\\\n & 47 & 43.1 \\\\\n & 48 & 45.4 \\\\\n & 49 & 44.8 \\\\\n\\cmidrule{2-3}\n & Mean$\\pm$std & $47.1 \\pm 2.2$ \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{Always-det (= majority-vote)} & 50.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-seed router performance under cross-split evaluation (8 seeds, generation-based, \\texttt{enable\\_thinking=False}). Step-level evaluation allows steps from the same episode in both train and validation sets (same-episode leakage). Episode-level evaluation holds out entire episodes; the resulting $47.1 \\pm 2.2\\%$ is below the 50\\% chance baseline. A text augmentation ablation (Table~\\ref{tab:text-augmentation}) confirms this failure persists under the current data distribution and augmentation regime.}\n\\label{tab:seed-robustness}\n\\end{table}\n\nThe contrast between step-level ($54.1 \\pm 5.4\\%$) and episode-level ($47.1 \\pm 2.2\\%$) evaluation reveals a generalization gap: the step-level signal likely reflects memorization of episode-specific context (enabled by same-episode leakage) rather than extraction of generalizable routing features. At episode level, the router performs below chance across all 8 seeds (range: 43.1\\%--49.6\\%). Paraphrase-based text augmentation (Table~\\ref{tab:text-augmentation}) from 25\\% to 800\\% ($32{\\times}$ range) provides no improvement, converging to the always-deterministic baseline ($50\\%$). Paraphrase augmentation inflates the majority class without generating novel routing patterns; genuine episode-level scaling (collecting more counterfactual pairs) remains an open question. With DAF $= 90.4\\%$ and all task types deterministic-majority (86:9 label ratio), always-deterministic trivially solves the episode-level routing problem, leaving the step-level router with no exploitable signal under current architectures.\n\n\\paragraph{Text augmentation ablation.} To test whether the episode-level generalization failure stems from data scarcity, we vary training set size from 25\\% to 800\\% of the original via paraphrase-based text augmentation (synonym substitution + template variation on step observations), holding the episode-level validation set fixed. This tests augmentation-based scaling, not genuine episode-level scaling (which would require new counterfactual collections). Table~\\ref{tab:text-augmentation} reports the results.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}rccc@{}}\n\\toprule\nScale & Samples & Det\\% & Ep.\\ Bal.\\ Acc.\\ (\\%) \\\\\n\\midrule\n25\\% & 433 & ${\\sim}90$ & $49.5 \\pm 0.3$ \\\\\n50\\% & 867 & ${\\sim}90$ & $51.5$ \\\\\n100\\% & 1{,}735 & 89.6 & $49.9 \\pm 0.1$ \\\\\n200\\% & 3{,}470 & 94.2 & $50.0 \\pm 0.0$ \\\\\n800\\% & 13{,}880 & ${\\sim}97.7$ & $51.0 \\pm 1.1$ \\\\\n\\midrule\nAlways-det & --- & --- & 50.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Text augmentation ablation: episode-level balanced accuracy across training set sizes (25\\%--800\\% of original via paraphrase, $32{\\times}$ range). Internal recall $= 0.0$ at all scales (complete majority-class collapse). Det\\%: fraction of deterministic-preferred labels in training data. The 50\\% scale is a single seed; all others report mean$\\pm$std across seeds.}\n\\label{tab:text-augmentation}\n\\end{table}\n\nAll scales hover at ${\\sim}50\\%$ episode-level balanced accuracy (equivalent to the always-deterministic baseline), with no monotonic improvement as data increases. Augmentation-based scaling provides no improvement at any scale; however, episode-level minority-class diversity remains a potential confound that cannot be resolved without collecting more internal-preferred episodes. The ground-truth internal-preferred rate (9/245 $= 3.7\\%$) means collecting 50 internal-preferred episodes would require approximately 1{,}350 paired episodes at current environment dynamics, a $5.5{\\times}$ expansion with diminishing return on a $9.6\\%$ signal. The failure points to a limitation of the current data distribution: when DAF $= 90.4\\%$ and all task types are deterministic-majority (86:9 label ratio), the episode-level routing problem is trivially solved by always choosing deterministic, and the step-level router finds no exploitable signal under the current architecture and data regime.\n\nAugmentation disproportionately increases the majority (deterministic) class: Det\\% rises from 89.6\\% at 100\\% to 94.2\\% at 200\\% and ${\\sim}97.7\\%$ at 800\\%. However, the complete collapse to majority-class prediction (internal recall $= 0.0$) occurs even at the smallest unaugmented scale (25\\%, ${\\sim}90\\%$ det); this is not an augmentation artifact. Balanced accuracy corrects for class imbalance by averaging per-class recall, so the metric itself is not biased by the skew.\n\nDecomposition metrics are stable under bootstrap resampling ($B{=}10{,}000$ resamples of the 245-episode dataset): DAF $= 90.4\\% \\pm 4.2\\%$ (95\\% CI $[81.1\\%, 99.0\\%]$); Pearson $r = 0.975 \\pm 0.011$ (95\\% CI $[0.952, 0.995]$). The death avoidance dominance finding is robust to both resampling and split perturbation.\n\n\\paragraph{Per-task-type evaluation breakdown.} To test whether the router learns transferable routing strategies or merely task-type classification, we evaluate existing checkpoints (8 seeds) separately on each of the 11 task types. Of the 11 task types, 7 have \\emph{all-deterministic} labels (no internal-preferred episodes exist), making balanced accuracy undefined; the router has nothing to learn beyond the trivial always-deterministic default. For the remaining 4 task types where both classes are present, balanced accuracy ranges from 50.0\\% to 73.0\\%, but this apparent signal does not indicate cross-task-type routing transfer: the router is effectively classifying task types (which correlate with death risk) rather than extracting a generalizable routing strategy. This complements the text augmentation ablation: routing signal does not transfer across task types because the signal \\emph{is} the task type, i.e., whether a given task carries death risk. The 4B capacity scaling result (Appendix~\\ref{app:ablations}) suggests capacity is one factor, but even 4B's $59.0\\%$ episode-level accuracy does not demonstrate cross-task-type transfer.\n\n\\section{Penalty Sensitivity Analysis}\n\\label{app:penalty}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}rrr@{}}\n\\toprule\n$P$ & DAF($P$) & 95\\% CI \\\\\n\\midrule\n0 & 7.4\\% & [$-39.4$, $82.5$] \\\\\n1 & 14.8\\% & [$-28.6$, $89.6$] \\\\\n5 & 35.4\\% & [$-1.8$, $92.7$] \\\\\n10 & 50.4\\% & [$18.5$, $93.3$] \\\\\n25 & 70.7\\% & [$48.0$, $96.3$] \\\\\n50 & 82.6\\% & [$67.2$, $98.2$] \\\\\n100\\textsuperscript{*} & 90.4\\% & [$81.1$, $99.0$] \\\\\n200 & 94.9\\% & [$89.9$, $99.5$] \\\\\n500 & 97.9\\% & [$95.7$, $99.8$] \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Sensitivity of DAF to death penalty magnitude $P$. DAF$(P) = 1 - \\Delta_{\\text{nd}} / \\Delta_{\\text{full}}(P)$, where $\\Delta_{\\text{full}}(P) \\approx \\delta \\cdot P + \\Delta_{\\text{nd}}$, $\\delta = 0.2653$ is the death-rate differential, and $\\Delta_{\\text{nd}} = 2.84$ (strict neither-died filtering). Recomputed from 245 episode-level data; bootstrap 95\\% CIs ($B{=}10{,}000$). \\textsuperscript{*}Default setting.}\n\\label{tab:penalty-sensitivity}\n\\end{table}\n\nThe non-death score gap $\\Delta_{\\text{nd}} = 2.84$ is invariant across penalty levels; it depends only on surviving-episode performance, not on $P$. As $P$ increases, $\\Delta_{\\text{full}}$ grows ($16.33$ at $P{=}50$, $29.60$ at $P{=}100$, $56.13$ at $P{=}200$) while $\\Delta_{\\text{nd}}$ remains fixed, mechanically increasing DAF.\n\n\\paragraph{Mechanism boundary: death specificity.}\nThe $r = 0.97$ correlation between per-task death-rate differential and $\\Delta_{\\text{full}}$ is specific to catastrophic death (score $= -100$). Broader failure definitions dissolve the correlation entirely: defining ``failure'' as any non-positive score ($T{=}0$) yields $r = -0.13$ ($p = 0.70$), because non-death episodes show near-zero performance differential between strategies ($\\Delta_{\\text{nd}} = 2.84$). Table~\\ref{tab:penalty-correlation} quantifies this specificity across penalty magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}rccl@{}}\n\\toprule\n$P$ & $r$ & $p$ & Sig.\\ ($\\alpha{=}0.05$) \\\\\n\\midrule\n1 & $-0.44$ & $0.178$ & No \\\\\n5 & $-0.29$ & $0.382$ & No \\\\\n10 & $-0.08$ & $0.813$ & No \\\\\n25 & $0.51$ & $0.108$ & No \\\\\n50 & $0.86$ & $0.0006$ & Yes \\\\\n100\\textsuperscript{*} & $0.97$ & $8 \\times 10^{-7}$ & Yes \\\\\n200 & $0.99$ & $1 \\times 10^{-9}$ & Yes \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Pearson $r$ between per-task death-rate differential and $\\Delta_{\\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \\geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \\textsuperscript{*}Default ScienceWorld setting.}\n\\label{tab:penalty-correlation}\n\\end{table}\n\nThis sharpens our central finding: death is not merely the dominant component of routing signal; it is effectively the \\emph{only} component that generates differential routing signal in ScienceWorld. At low penalties, the death contribution is small and $\\Delta_{\\text{full}}$ reduces to $\\Delta_{\\text{nd}} \\approx 2.84$, which is near-uniform across task types ($\\text{mean non-death gap} = -1.19$ excluding the \\texttt{find-non-living-thing} outlier); consequently, death-rate differential has no predictive power. As $P$ increases, the death term dominates $\\Delta_{\\text{full}}$, and the correlation sharpens because death rates \\emph{are} the performance gap. The DAF values in Table~\\ref{tab:penalty-sensitivity} increase monotonically with $P$, but this is a mathematical consequence of the decomposition ($\\text{DAF} = \\delta P / (\\delta P + \\Delta_{\\text{nd}})$), not evidence of mechanism robustness.\n\n\\section{Cross-Environment Details}\n\\label{app:cross-env-details}\n\nFigure~\\ref{fig:signal-reversal} and Table~\\ref{tab:cross-env} summarize the label distributions across all three environments.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/signal_reversal.pdf}\n\\caption{Cross-environment label distributions. ScienceWorld and ALFWorld both show deterministic preference, but through different mechanisms: death avoidance (ScienceWorld) vs.\\ information asymmetry from admissible-action access (ALFWorld). MATH shows balanced labels, confirming no routing signal without catastrophic failure.}\n\\label{fig:signal-reversal}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nEnvironment & $N$ & Det\\% & Int\\% & NoPref\\% & Death? \\\\\n\\midrule\nScienceWorld & 245 & 35.1 & 3.7 & 61.2 & Yes ($-100$) \\\\\nMATH & 795 & 7.3 & 8.3 & 84.4 & No \\\\\nALFWorld & 135 & 25.9 & 1.5 & 72.6 & No\\textsuperscript{$\\dagger$} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-environment label distribution. ``Deterministic'' denotes qualitatively different computation modes: ScienceWorld = oracle simulator with ground-truth state; MATH = Python code interpreter; ALFWorld = admissible-action enumeration. $\\dagger$\\,ALFWorld's deterministic advantage stems from information asymmetry, not death avoidance.}\n\\label{tab:cross-env}\n\\end{table}\n\nTable~\\ref{tab:alfworld-pertask} provides the per-task-type breakdown for ALFWorld. Unlike ScienceWorld, ALFWorld has no death mechanism ($\\delta = 0$, DAF $= 0\\%$); the entire performance gap $\\Delta_{\\text{full}}$ reflects information asymmetry from admissible-action access. \\texttt{pick\\_and\\_place} shows the strongest effect ($\\Delta = 0.563$, 18 of 32 episodes det-preferred), while \\texttt{pick\\_two\\_obj\\_and\\_place} shows the weakest ($\\Delta = 0.087$), consistent with multi-object tasks requiring more sequential reasoning that admissible actions alone cannot resolve. Only \\texttt{pick\\_heat\\_then\\_place} has a 95\\% CI crossing zero ($n{=}16$).\n\n\\begin{table}[h]\n\\centering\n\\scriptsize\n\\setlength{\\tabcolsep}{2.5pt}\n\\begin{tabular}{@{}lrcccc@{}}\n\\toprule\nTask Type & $n$ & Succ\\%\\textsubscript{int} & Succ\\%\\textsubscript{det} & D / I / N & $\\Delta_{\\text{full}}$ \\\\\n\\midrule\npick\\_and\\_place       & 32 & 0.0  & 56.3 & 18 / 0 / 14 & $+0.563$ \\\\\nlook\\_at\\_obj\\_in\\_light & 13 & 15.4 & 38.5 & 3 / 0 / 10  & $+0.231$ \\\\\npick\\_cool\\_then\\_place & 24 & 0.0  & 16.7 & 4 / 0 / 20  & $+0.167$ \\\\\npick\\_clean\\_then\\_place & 27 & 3.7  & 18.5 & 5 / 1 / 21  & $+0.148$ \\\\\npick\\_heat\\_then\\_place & 16 & 6.3  & 18.8 & 3 / 1 / 12  & $+0.125$ \\\\\npick\\_two\\_obj\\_and\\_place & 23 & 0.0 & 8.7  & 2 / 0 / 21  & $+0.087$ \\\\\n\\midrule\n\\textbf{All (6 types)} & \\textbf{135} & \\textbf{3.0} & \\textbf{27.4} & \\textbf{35 / 2 / 98} & $\\mathbf{+0.244}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\\Delta_{\\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\\Delta_{\\text{full}}$ descending.}\n\\label{tab:alfworld-pertask}\n\\end{table}\n\n\\paragraph{MATH subset composition.}\nThe $N{=}795$ MATH problems span two categories from the MATH test set~\\citep{math-2021} (Levels 4--5): Algebra (585, 73.6\\%) and Counting \\& Probability (210, 26.4\\%). The category imbalance reflects the relative sizes in the original test set.\n\n\\section{Cross-Model Verification}\n\\label{app:cross-model}\n\nWe replicate the counterfactual analysis with Llama-3.1-8B-Instruct across all 11 task types ($N{=}220$ episode pairs, 20 per type; Table~\\ref{tab:cross-model-detail}).\nThe internal strategy dies in $41.4\\%$ of episodes versus $11.4\\%$ for deterministic (death-rate differential $+30.0$~pp), with 83 deterministic-preferred, 3 internal-preferred (1.4\\%, all death-asymmetry reversals), and 134 no-preference labels.\nBoth models exhibit nearly identical internal vulnerability (${\\sim}$42\\%: Qwen $42.9\\%$, Llama $41.4\\%$), confirming that death-prone failure is empirically dominated by the task environment rather than model-specific factors. The differential magnitude varies ($+26.5$~pp Qwen, $+30.0$~pp Llama) because deterministic strategy safety is model-dependent ($16.3\\%$ vs.\\ $11.4\\%$), but directional consistency is 100\\% (10/10 death-prone tasks in both models).\n\\texttt{identify-life-stages-1} shows cross-model precision matching ($55\\%$/$10\\%$/$+45$~pp in both models).\n\\texttt{find-non-living-thing} shows zero deaths in both models, consistent with its majority-class answer distribution.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lrrrl@{}}\n\\toprule\nTask & Int\\% & Det\\% & $\\Delta$\\,pp & D / I / N \\\\\n\\midrule\nidentify-life-stages-1 & 55 & 10 & +45 & 9 / 0 / 11 \\\\\nfreeze & 45 & 0 & +45 & 9 / 0 / 11 \\\\\ngrow-fruit & 45 & 5 & +40 & 8 / 0 / 12 \\\\\nidentify-life-stages-2 & 45 & 5 & +40 & 8 / 0 / 12 \\\\\nmeasure-melting-point & 50 & 15 & +35 & 9 / 0 / 11 \\\\\nlifespan-longest & 35 & 5 & +30 & 7 / 1 / 12 \\\\\nlifespan-l-then-s & 50 & 20 & +30 & 6 / 0 / 14 \\\\\nchemistry-mix & 45 & 20 & +25 & 5 / 0 / 15 \\\\\ninclined-plane & 45 & 20 & +25 & 6 / 0 / 14 \\\\\nfind-animal & 40 & 25 & +15 & 6 / 2 / 12 \\\\\nfind-non-living-thing & 0 & 0 & 0 & 10 / 0 / 10 \\\\\n\\midrule\n\\textbf{Aggregate} & \\textbf{41.4} & \\textbf{11.4} & \\textbf{+30.0} & \\textbf{83 / 3 / 134} \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\\Delta$ DR descending.}\n\\label{tab:cross-model-detail}\n\\end{table}\n\n\\paragraph{Cross-model and cross-environment summary.}\nTable~\\ref{tab:cross-model-env} consolidates replication results across model families and environments.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcrrrccc}\n\\toprule\nModel & Environment & $n$ & Int DR & Det DR & $\\Delta$DR & DAF & DAF 95\\% CI & Signal \\\\\n\\midrule\nQwen2.5-7B & ScienceWorld & 245 & 42.9\\% & 16.3\\% & +26.5 & 90.4\\% & [81.1, 99.0] & death \\\\\nLlama-3.1-8B & ScienceWorld & 220 & 41.4\\% & 11.4\\% & +30.0 & 88.2\\% & [80.2, 95.1] & death \\\\\nGemma-2-9B-it & ScienceWorld & 220 & 36.4\\% & 14.1\\% & +22.3 & 89.7\\% & [79.5, 98.4] & death \\\\\nQwen2.5-72B & ScienceWorld & 255 & 30.6\\% & 2.75\\% & +27.8 & 92.4\\% & --- & death \\\\\n\\midrule\nQwen2.5-7B & ALFWorld & 135 & 0\\% & 0\\% & 0 & 0\\% & --- & info-asym \\\\\nLlama-3.1-8B & ALFWorld & 135 & 0\\% & 0\\% & 0 & 0\\% & --- & info-asym \\\\\n\\midrule\nQwen2.5-7B & MATH & 795 & N/A & N/A & N/A & N/A & N/A & none \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-model and cross-environment replication summary. \\textbf{ScienceWorld}: death dominance replicates across three model families in the 7--9B range and persists under $10{\\times}$ scaling (72B); DAF 95\\% CIs from non-clustered episode-level bootstrap ($B{=}10{,}000$). \\textbf{ALFWorld}: DAF $= 0\\%$ (no death mechanism); routing signal arises from information asymmetry. \\textbf{MATH}: no routing signal without catastrophic failure. Signal column: diagnosed routing mechanism. DR = death rate. Gemma-2's wider CI reflects one zero-death task type (\\texttt{find-non-living-thing}); excluding it yields DAF $= 99.9\\%$ $[99.7, 100.0]$.}\n\\label{tab:cross-model-env}\n\\end{table}\n\n\\section{Failure Mode Analysis}\n\\label{app:failure-modes}\n\nAll 105 internal-strategy deaths (100\\%) are triggered by the same action pattern: \\texttt{focus on [object]}. In ScienceWorld, \\texttt{focus on} is the answer-submission action (equivalent to ``this is my final answer''); the LLM agent systematically misuses it as a general interaction or exploration command, and applies it to irrelevant targets (rooms, doors, inventory items). Each such execution submits an incorrect answer and triggers the $-100$ death penalty. Within death episodes, both strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$); the internal strategy's higher death count (105 vs.\\ 40 for deterministic) reflects how often each strategy enters catastrophic states, not different action selection within those states.\n\nManual inspection identifies four failure categories: (A) no task awareness, where the agent executes \\texttt{focus on} without reading the task; (B) task-aware but lacking action grounding, where the agent correctly identifies the objective but cannot map it to valid action primitives; (D) genuine attempts with execution failure; and (E) initial progress wasted by early errors. Category B dominates: agents demonstrate task comprehension but systematically fail to translate it into correct ScienceWorld actions. This taxonomy was produced by a single annotator; no inter-annotator agreement was computed. The categories are intended as qualitative illustrations, not as formal labels with reliability guarantees.\n\\label{tab:death-taxonomy}\n\n\\paragraph{Representative examples.}\n\\emph{Category A} (no task awareness): In a \\texttt{chemistry-mix} episode, the agent immediately executes \\texttt{focus on kitchen}, \\texttt{focus on door}, \\texttt{focus on inventory} without reading the task, dying on the first \\texttt{focus on} call. \\emph{Category B} (comprehension without grounding): In a \\texttt{lifespan-longest-lived} episode, the agent correctly identifies that it must compare animal lifespans and reasons about which animal lives longest, but then executes \\texttt{focus on oak tree} (a non-animal object in the room) instead of navigating to find the target animal, triggering death.\n\n\\paragraph{Action distribution analysis.}\nFigure~\\ref{fig:death-action-dist} shows the action distribution in death versus non-death episodes for the internal strategy; both are dominated by \\texttt{connect} actions, with \\texttt{focus on} moderately more frequent in death episodes ($5.4\\%$ vs.\\ $3.4\\%$). Crucially, Figure~\\ref{fig:death-comparison} reveals that within death episodes, internal and deterministic strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$). The survival gap (105 vs.\\ 40 deaths) therefore reflects how often each strategy enters catastrophic states, not how it behaves within those states. Among fatal \\texttt{focus on} targets, \\texttt{workshop} remains the most frequent (20.0\\%), followed by \\texttt{inventory} (17.1\\%) and \\texttt{kitchen} (10.5\\%), indicating a systematic object bias rather than random exploration. Figure~\\ref{fig:death-timeline} visualizes the temporal pattern: agents execute long sequences of \\texttt{connect} actions before a terminal \\texttt{focus on} triggers death, typically in the final 1--3 steps.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/death_action_distribution.pdf}\n\\caption{Action distribution for the internal (LLM) strategy in death ($n{=}105$) vs.\\ non-death ($n{=}140$) episodes. Left: full distribution (both dominated by \\texttt{connect}). Right: non-\\texttt{connect} actions zoomed. \\texttt{focus on} is moderately more frequent in death episodes ($5.4\\%$ vs.\\ $3.4\\%$), while non-death episodes show higher rates of observation and object interaction.}\n\\label{fig:death-action-dist}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/death_action_timeline.pdf}\n\\caption{Step-by-step action sequences for 6 representative death episodes. The fatal \\texttt{focus on} action (marked with arrow) consistently appears in the final steps after long \\texttt{connect} sequences, and illustrates the ``connect loop $\\to$ fatal focus'' pattern. Examples are drawn from the full 30-task dataset for task-type diversity; the pattern is identical in the 11-task analysis subset.}\n\\label{fig:death-timeline}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/death_action_comparison.pdf}\n\\caption{Non-\\texttt{connect} action distribution comparison between internal (left) and deterministic (right) strategies. Within death episodes, both strategies exhibit comparable \\texttt{focus on} rates (${\\sim}5\\%$); the internal strategy's higher death count (105 vs.\\ 40) reflects more frequent entry into catastrophic states, not different action selection within those states.}\n\\label{fig:death-comparison}\n\\end{figure}\n\n\\section{Grounding Ablation}\n\\label{app:grounding-ablation}\n\nWe test whether directly intervening on the dominant death action (\\texttt{focus on}) eliminates death vulnerability on the 10 death-prone tasks (baseline 48.0\\%, $n{=}200$).\n\n\\paragraph{Prompt warning.} Adding an explicit system prompt (``use \\texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\\% ($\\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\\texttt{identify-life-stages-1}: 35\\%$\\to$50\\%; \\texttt{identify-life-stages-2}: 25\\%$\\to$70\\%), where explicit mention of the dangerous action may have increased its salience.\n\n\\paragraph{Action-space filtering.} Blocking \\texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\\% ($\\Delta = -19$~pp). The zero-passthrough rate suggests \\texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.\n\n\\paragraph{Per-task variation.} Under filtering, \\texttt{identify-life-stages} and \\texttt{inclined-plane} approach deterministic-level safety (${\\sim}$15--20\\% DR), while \\texttt{chemistry-mix} and \\texttt{find-animal} remain at 35--40\\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \\texttt{focus on} to incorrect objects.\n\n\\section{Ablation Studies}\n\\label{app:ablations}\n\n\\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\\ref{tab:capacity}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nModel & Step Bal.\\ Acc.\\ (\\%) & Ep.\\ Bal.\\ Acc.\\ (\\%) \\\\\n\\midrule\nQwen3-0.6B & $56.4 \\pm 3.5$ & $50.7 \\pm 2.6$ \\\\\nQwen3-1.7B & $58.2 \\pm 4.0$ & $43.1 \\pm 1.0$ \\\\\nQwen3-4B & $59.2 \\pm 3.5$ & $\\mathbf{59.0 \\pm 1.9}$ \\\\\n\\midrule\nAlways-det & 50.0 & 50.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Capacity scaling: step-level and episode-level balanced accuracy (4 seeds, identical configuration across all scales). Step-level accuracy is flat ($56$--$59\\%$, within seed variance). At episode level, only 4B breaks the random baseline ($59.0\\%$, $p < 0.005$).}\n\\label{tab:capacity}\n\\end{table}\n\nStep-level balanced accuracy is flat across scales ($56$--$59\\%$, within seed variance); step-level discrimination is not capacity-sensitive. At episode level, only 4B breaks the random baseline ($59.0 \\pm 1.9\\%$, $p < 0.005$); 0.6B and 1.7B remain at or below chance. The 1.7B model's below-chance episode-level accuracy ($43.1\\%$) may reflect overfitting to spurious step-level correlations that anti-correlate with episode outcomes; without per-class confusion matrices at this scale, this remains a hypothesis. The dominant explanation across scales is that death avoidance constitutes a task-type-level binary signal that a step-level router cannot exploit efficiently.\n\n\\paragraph{Generative router.} A generative routing model trained with explicit routing labels achieves balanced accuracy of 46.7\\%, confirming that the routing bottleneck is signal-limited, not architecture-limited.\n\n\\paragraph{Leave-one-task-type-out routing.} Under leave-one-task-type-out evaluation, blind routing collapses to always-deterministic (balanced accuracy 50.0\\%); a keyword-based variant achieves 62.9\\% only through task-identity leakage, not genuine routing signal. A guided router evaluated under the same protocol confirms this: without task-type identifiers it achieves chance accuracy (50.0\\%), and leaking task names raises this to 62.9\\%, confirming that the only learnable routing feature is task-type identity.\n\n\\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\\%, episode balanced accuracy 50.0\\%, internal recall 0\\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.\n\n\\paragraph{Reasoning depth.} An ablation comparing chain-of-thought reasoning against direct-answer generation on 6 task types ($n{=}120$ episodes per condition, 6 tasks $\\times$ 20 episodes per task) found no significant difference (Mann--Whitney $p > 0.26$, $|d| \\leq 0.31$) and near-identical death rates (41.8\\% vs.\\ 42.5\\%); reasoning depth does not meaningfully alter internal-mode outcomes.\n\n\\section{Threshold Routing Analysis}\n\\label{sec:threshold-routing}\n\nGiven per-task death risk knowledge, we test whether a simple threshold routing strategy can outperform always-deterministic. For each threshold $t \\in [0, 1]$, we route to internal if the per-task internal death rate $\\leq t$, otherwise to deterministic, and sweep all thresholds to find the optimal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\nStrategy & Mean Score & Death Rate & $\\Delta$ vs Det \\\\\n\\midrule\nAlways-det & $-9.47$ & $0.163$ & $0.00$ \\\\\nOptimal threshold ($t{=}0$) & $-11.03$ & $0.155$ & $-1.56$ \\\\\nAlways-internal & $-39.07$ & $0.429$ & $-29.60$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Death-risk threshold routing analysis on 245 episodes. The optimal threshold routes only \\texttt{find-non-living-thing} (the sole zero-death task) to internal, with all other tasks routed to deterministic. Bootstrap 95\\% CI for the difference: $[-8.87, +5.92]$.}\n\\label{tab:threshold-routing}\n\\end{table}\n\nEven with perfect per-task death risk knowledge, threshold routing cannot outperform always-deterministic. The sole zero-death task achieves higher scores under deterministic (+28.5) than internal (+18.9), leaving no room for a beneficial mixed strategy.\n\n\\section{Practitioner Decision Framework}\n\\label{app:decision-framework}\n\nGiven a new interactive environment, the following three-stage procedure diagnoses whether learned routing adds value over a fixed deterministic strategy.\n\n\\paragraph{Stage 1: Pilot collection (${\\sim}$50 episodes).}\nRun pure-internal and pure-deterministic strategies on a representative sample (${\\sim}$50 episode pairs). Compute the death-rate differential $\\Delta\\text{DR} = \\text{DR}_{\\text{int}} - \\text{DR}_{\\text{det}}$.\n\n\\paragraph{Stage 2: Death dominance check.}\nIf $\\Delta\\text{DR} > 15$~pp, death asymmetry is likely the dominant routing signal. Compute the death-label fraction $f_{\\text{death}}$: the proportion of non-tie routing labels where exactly one strategy dies.\n\n\\paragraph{Stage 3: Decision.}\nIf $f_{\\text{death}} > 75\\%$, the routing signal is death-dominated; a fixed deterministic strategy will match or exceed any learned router. If $f_{\\text{death}} < 50\\%$, diverse routing signals may justify a learned router. Between 50\\%--75\\%, collect additional episodes to reduce estimation noise before committing to router development.\n\n\\paragraph{Retrospective validation.}\nAll four experimental conditions in this paper are correctly classified:\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lrrll@{}}\n\\toprule\nCondition & $\\Delta$DR & $f_{\\text{death}}$ & Prediction & Actual \\\\\n\\midrule\nQwen-7B & +26.5 & 78.9\\% & det-fixed & det wins \\\\\nLlama-8B & +30.0 & $>$75\\% & det-fixed & det wins \\\\\nQwen-72B & +27.8 & $>$75\\% & det-fixed & det wins \\\\\nMATH & +0.5 & 0\\% & router viable & no signal \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Retrospective validation of the decision framework. All four conditions are correctly classified (4/4).}\n\\label{tab:decision-framework}\n\\end{table}\n\nThe framework also predicts the inverted-U relationship between capability and death risk: below ${\\sim}$0.5B parameters, agents rarely reach dangerous states (13.3\\% death rate in a 15-episode pilot), so $\\Delta\\text{DR}$ is low and the framework would not recommend fixed-deterministic. Above ${\\sim}$7B, agents are capable enough to enter catastrophic states but not capable enough to avoid them, producing high $\\Delta\\text{DR}$.\n\n\\paragraph{Threshold calibration.} The thresholds above (15~pp, 75\\%, 50\\%) are illustrative, derived from ScienceWorld's specific reward structure (binary death penalty $P{=}100$, sparse terminal rewards). Environments with graded penalties, dense rewards, or qualitatively different failure modes may require different thresholds. Practitioners should calibrate these boundaries for their specific environment.\n\n\\section{Extended Validation of Excluded Tasks}\n\\label{app:extended-validation}\n\nTo verify that task exclusion does not bias toward death-prone tasks, we collect $n{=}20$ episodes for five representative excluded tasks spanning all exclusion categories (Table~\\ref{tab:extended-val}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcrrrrc}\n\\toprule\nTask & Category & $n$ & Int DR & Det DR & $\\Delta$DR & D/I/N \\\\\n\\midrule\nboil & dev-set & 20 & 55\\% & 25\\% & +30\\,pp & 6/0/14 \\\\\nmelt & dev-set & 20 & 45\\% & 20\\% & +25\\,pp & 7/2/11 \\\\\nfind-living-thing & taxonomic & 20 & 55\\% & 15\\% & +40\\,pp & 10/0/10 \\\\\nuse-thermometer & agent-floor & 20 & 50\\% & 20\\% & +30\\,pp & 7/1/12 \\\\\npower-component & agent-floor & 20 & 50\\% & 15\\% & +35\\,pp & 7/0/13 \\\\\n\\midrule\n\\textit{Mean (5 tasks)} & & 100 & 51.0\\% & 19.0\\% & +32.0\\,pp & 37/3/60 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Extended validation ($n{=}20$) of representative excluded task types. All five tasks confirm death asymmetry; mean $\\Delta$DR $= +32.0$\\,pp is consistent with the $n{=}5$ prescreening estimate for these same tasks (Table~\\ref{tab:excluded-death}).}\n\\label{tab:extended-val}\n\\end{table}\n\nNotably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\\ref{tab:per-task}), indicating that excluded tasks are \\emph{more} death-dominated than included tasks---the opposite of a cherry-picking bias.\n\n\\section{Agent Prompt Templates}\n\\label{app:prompt-templates}\n\nBelow we show the complete prompt templates used for agent interaction in ScienceWorld. Both the internal (ReAct) and deterministic strategies share the same system prompt but differ in the user message template.\n\n\\paragraph{System prompt (shared).} Used for all ScienceWorld agent interactions across both computation modes.\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nYou are an agent interacting with a ScienceWorld text\nenvironment. Your goal is to complete the given task by\nchoosing actions from the available action list.\n\nUse the following format for each step:\nThought: &lt;your reasoning about what to do next>\nAction: &lt;exact action string from the valid actions list>\n\nRules:\n- You MUST choose an action from the valid actions list.\n  Do not invent actions.\n- Think step by step about what physical/scientific\n  process is needed.\n- Pay attention to the current observation for clues\n  about object states.\n\\end{tcblisting}\n\n\\paragraph{Internal (ReAct) user template.} At each step, the agent receives the current observation, valid action list, and recent action history, and must select a single action.\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nCurrent observation:\n{observation}\n\nValid actions:\n{valid_actions_str}\n\nPrevious actions taken: {history_str}\n\nChoose your next action.\n\\end{tcblisting}\n\n\\paragraph{Deterministic candidate generation template.} For the deterministic strategy, the agent generates ranked candidate actions instead of selecting one; these candidates are then evaluated via simulator forking (\\S\\ref{sec:method}).\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nCurrent observation:\n{observation}\n\nValid actions:\n{valid_actions_str}\n\nPrevious actions taken: {history_str}\n\nGenerate the top 3 most promising actions from the valid\nactions list, ranked by how likely they are to make\nprogress on the task. Output exactly 3 actions, one per\nline, in this format:\n1. &lt;action>\n2. &lt;action>\n3. &lt;action>\n\\end{tcblisting}\n\n\\paragraph{Reflexion self-reflection prompt.} After a failed episode, the Reflexion agent (\\S\\ref{sec:agent-improvement}) generates a reflection that is injected into subsequent trial attempts as additional system context.\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nYou just completed an episode in a ScienceWorld text\nenvironment but failed.\n\nTask: {task_name}\nFinal score: {final_score}\nOutcome: {outcome}\nNumber of steps taken: {num_steps}\n\nHere is a summary of your actions:\n{action_summary}\n\nAnalyze why this episode failed and provide a short\nstrategy for the next attempt. Focus on:\n1. What went wrong (wrong sequence, missed key step,\n   dangerous action)?\n2. What should be done differently next time?\n\nKeep your reflection under 200 words.\n\\end{tcblisting}\n\n\\paragraph{Grounding warning (ablation).} The prompt warning condition in the grounding ablation (Appendix~\\ref{app:grounding-ablation}) appends the following to the shared system prompt:\n\n\\begin{tcblisting}{listing only, colback=gray!5!white, colframe=gray!75!black,\n  listing options={basicstyle=\\small\\ttfamily,breaklines=true,columns=fullflexible},\n  left=2mm, right=2mm, top=1mm, bottom=1mm}\nCRITICAL SAFETY RULE: The 'focus on [object]' action is\nONLY for submitting your final answer. Do NOT use\n'focus on' to examine, inspect, or interact with objects\nduring exploration. Using 'focus on' on the wrong object\nwill cause irreversible failure. Use 'look at',\n'examine', or 'pick up' instead for exploration.\n\\end{tcblisting}\n\n\\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \\emph{select} one action (ReAct), while the deterministic strategy asks it to \\emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.\n\n\\input{responsibleNLPchecklist}\n\n\\end{document}\n",
      "numLines": 887,
      "startLine": 1,
      "totalLines": 887
    }
  },
  "sourceToolAssistantUUID": "0585d0b5-af02-4841-b6e5-290de6e709de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 40 · 2026-05-21T13:43:46.711Z_

```json
{
  "parentUuid": "c9a9e593-853f-44a1-a2e3-19716cae8a1a",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "69279e56-9fca-41c9-8f21-81433cc1f6f9",
  "timestamp": "2026-05-21T13:43:46.711Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 41_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 15 warnin…",
  "leafUuid": "69279e56-9fca-41c9-8f21-81433cc1f6f9",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 42_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Assistant

_source line 43 · 2026-05-21T13:43:51.063Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the .tex files. Let me systematically audit the paper across all dimensions specified.

Let me also do some targeted searches for AI-style issues.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "69279e56-9fca-41c9-8f21-81433cc1f6f9",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "54149a8d-67ff-4cc3-b356-1a438799c6a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-21T13:43:51.641Z_

现在执行针对性文本扫描。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "54149a8d-67ff-4cc3-b356-1a438799c6a9",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "2c560163-6d6d-49f4-a7b6-f7f80f9e113e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 45 · 2026-05-21T13:43:54.084Z_

<details open><summary>🔧 Tool call — Grep · `toolu_019f1UeX7Fd32GLTEYsfRgbM`</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c560163-6d6d-49f4-a7b6-f7f80f9e113e",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "51aab34a-9a56-465a-9791-0f62acb54a2e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 46 · 2026-05-21T13:44:01.263Z_

<details><summary>↩ Tool result · `toolu_01Bi5v3ahJnELtQFAytLvrte`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:12:\paragraph{Adaptive Computation and Routing.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:13:Adaptive routing traces back to learned halting policies \citep{graves2016act}. In the LLM era, CogRouter \citep{cogrouter-2026} adapts reasoning depth per step, ARES \citep{ares-2026} selects among reasoning effort levels, Mixture-of-Recursions \citep{mixture-of-recursions-2025} learns token-level recursion depths, and MTRouter \citep{mtrouter-2026} addresses multi-turn routing.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:18:Prior work generates counterfactual explanations by perturbing individual actions \citep{olson2021counterfactual, gajcin2023counterfactual, amitai2024explaining}; recent extensions target LLM agents~\citep{pona2025abstract,axis-2026,cso-2026}. We instead execute complete episodes under two strategies to decompose routing signal \emph{before} training.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:20:\paragraph{LLM Agent Environments and Reasoning.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:21:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:114:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:49:Our counterfactual analysis compares pure strategies (always-internal vs.\ always-deterministic). In mixed routing, the router can selectively invoke deterministic mode on high-risk steps, potentially reducing death asymmetry. Thus, DAF${=}90.4\%$ represents an upper bound on death avoidance's contribution to optimized routing; the actual contribution under mixed strategies may be lower.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:56:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:126:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:157:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:161:\paragraph{Task selection and anti-cherry-picking.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:255:\noindent All methods confirm significance with $p < 0.01$, and the 95\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:295:{\footnotesize $^\dagger$Only death-free task; contributes all score-comparison labels. Sorted by $|\Delta|$ descending.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:411:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:462:\caption{Sensitivity of DAF to death penalty magnitude $P$. DAF$(P) = 1 - \Delta_{\text{nd}} / \Delta_{\text{full}}(P)$, where $\Delta_{\text{full}}(P) \approx \delta \cdot P + \Delta_{\text{nd}}$, $\delta = 0.2653$ is the death-rate differential, and $\Delta_{\text{nd}} = 2.84$ (strict neither-died filtering). Recomputed from 245 episode-level data; bootstrap 95\% CIs ($B{=}10{,}000$). \textsuperscript{*}Default setting.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:487:\caption{Pearson $r$ between per-task death-rate differential and $\Delta_{\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \textsuperscript{*}Default ScienceWorld setting.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:542:\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\Delta_{\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\Delta_{\text{full}}$ descending.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:580:\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\Delta$ DR descending.}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:615:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:650:\paragraph{Prompt warning.} Adding an explicit system prompt (``use \texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\% ($\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\texttt{identify-life-stages-1}: 35\%$\to$50\%; \texttt{identify-life-stages-2}: 25\%$\to$70\%), where explicit mention of the dangerous action may have increased its salience.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:652:\paragraph{Action-space filtering.} Blocking \texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\% ($\Delta = -19$~pp). The zero-passthrough rate suggests \texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:654:\paragraph{Per-task variation.} Under filtering, \texttt{identify-life-stages} and \texttt{inclined-plane} approach deterministic-level safety (${\sim}$15--20\% DR), while \texttt{chemistry-mix} and \texttt{find-animal} remain at 35--40\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \texttt{focus on} to incorrect objects.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:659:\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\ref{tab:capacity}).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:683:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:685:\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\%, episode balanced accuracy 50.0\%, internal recall 0\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:882:\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \emph{select} one action (ReAct), while the deterministic strategy asks it to \emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:8:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:57:Yes. We specify vLLM for inference, LoRA for fine-tuning, and provide all relevant configuration parameters (Table~\ref{tab:hyperparams}). Model identifiers are given precisely (e.g., Qwen2.5-7B-Instruct, Qwen3-1.7B).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:76:Yes. Claude (Anthropic) was used for code development, data analysis scripting, and manuscript drafting. All experimental design, scientific claims, and interpretation of results were conducted by the authors.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:29:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:64:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:8:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:12:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f85f3215-af19-4877-99e2-ab5ba00d98bc",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "a67db42b-b9ea-43cd-aa78-bbbf82b25e1e",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:12:\\paragraph{Adaptive Computation and Routing.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:13:Adaptive routing traces back to learned halting policies \\citep{graves2016act}. In the LLM era, CogRouter \\citep{cogrouter-2026} adapts reasoning depth per step, ARES \\citep{ares-2026} selects among reasoning effort levels, Mixture-of-Recursions \\citep{mixture-of-recursions-2025} learns token-level recursion depths, and MTRouter \\citep{mtrouter-2026} addresses multi-turn routing.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:18:Prior work generates counterfactual explanations by perturbing individual actions \\citep{olson2021counterfactual, gajcin2023counterfactual, amitai2024explaining}; recent extensions target LLM agents~\\citep{pona2025abstract,axis-2026,cso-2026}. We instead execute complete episodes under two strategies to decompose routing signal \\emph{before} training.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:20:\\paragraph{LLM Agent Environments and Reasoning.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:21:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:114:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:49:Our counterfactual analysis compares pure strategies (always-internal vs.\\ always-deterministic). In mixed routing, the router can selectively invoke deterministic mode on high-risk steps, potentially reducing death asymmetry. Thus, DAF${=}90.4\\%$ represents an upper bound on death avoidance's contribution to optimized routing; the actual contribution under mixed strategies may be lower.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:56:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:126:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:157:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:161:\\paragraph{Task selection and anti-cherry-picking.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:255:\\noindent All methods confirm significance with $p < 0.01$, and the 95\\% CI $[0.73, 1.00]$ excludes zero by a wide margin. With $K{=}11$ task types, ICC estimation itself carries substantial uncertainty; the high within-task consistency of death patterns (all-or-nothing per task type) suggests high ICC, which explains the CI narrowing under cluster resampling.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:295:{\\footnotesize $^\\dagger$Only death-free task; contributes all score-comparison labels. Sorted by $|\\Delta|$ descending.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:411:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:462:\\caption{Sensitivity of DAF to death penalty magnitude $P$. DAF$(P) = 1 - \\Delta_{\\text{nd}} / \\Delta_{\\text{full}}(P)$, where $\\Delta_{\\text{full}}(P) \\approx \\delta \\cdot P + \\Delta_{\\text{nd}}$, $\\delta = 0.2653$ is the death-rate differential, and $\\Delta_{\\text{nd}} = 2.84$ (strict neither-died filtering). Recomputed from 245 episode-level data; bootstrap 95\\% CIs ($B{=}10{,}000$). \\textsuperscript{*}Default setting.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:487:\\caption{Pearson $r$ between per-task death-rate differential and $\\Delta_{\\text{full}}(P)$ across penalty magnitudes. The correlation is non-significant at low penalties and emerges at $P \\geq 50$, which reflects the transition from non-death-dominated to death-dominated score gaps. \\textsuperscript{*}Default ScienceWorld setting.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:542:\\caption{Per-task-type decomposition for ALFWorld (135 games, Qwen2.5-7B-Instruct). D/I/N: deterministic-preferred / internal-preferred / no-preference. No death mechanism exists; $\\Delta_{\\text{full}}$ is driven entirely by information asymmetry from admissible-action access. Sorted by $\\Delta_{\\text{full}}$ descending.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:580:\\caption{Per-task Llama-3.1-8B cross-model replication ($N{=}20$ per task). D/I/N: deterministic-preferred / internal-preferred / no-preference. Sorted by $\\Delta$ DR descending.}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:615:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:650:\\paragraph{Prompt warning.} Adding an explicit system prompt (``use \\texttt{focus on} only for final answers'') reduces aggregate death rate to 37.0\\% ($\\Delta = -11$~pp). Both identification tasks exhibit ironic effects (\\texttt{identify-life-stages-1}: 35\\%$\\to$50\\%; \\texttt{identify-life-stages-2}: 25\\%$\\to$70\\%), where explicit mention of the dangerous action may have increased its salience.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:652:\\paragraph{Action-space filtering.} Blocking \\texttt{focus on} during the exploration phase yields 379 blocks across 200 episodes with zero leaks and zero passthroughs (the agent never persisted in retrying blocked actions), reducing death rate to 29.0\\% ($\\Delta = -19$~pp). The zero-passthrough rate suggests \\texttt{focus on} use is a shallow behavioral pattern rather than a deliberate strategy.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:654:\\paragraph{Per-task variation.} Under filtering, \\texttt{identify-life-stages} and \\texttt{inclined-plane} approach deterministic-level safety (${\\sim}$15--20\\% DR), while \\texttt{chemistry-mix} and \\texttt{find-animal} remain at 35--40\\%. Residual deaths occur during the answer-submission window, where the filter is inactive and agents submit \\texttt{focus on} to incorrect objects.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:659:\\paragraph{Capacity scaling.} We scale the implicit router from Qwen3-0.6B to Qwen3-4B and evaluate at both step and episode level (Table~\\ref{tab:capacity}).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:683:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:685:\\paragraph{Death-proximal labeling.} Training a router only on the $k$ steps preceding death events (rather than all steps) also collapses to majority-class prediction (step balanced accuracy 50.0\\%, episode balanced accuracy 50.0\\%, internal recall 0\\%), confirming that the absence of step-level signal is not an artifact of label dilution across long episodes.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:882:\\noindent The key difference between the two computation modes is the user message: the internal strategy asks the LLM to \\emph{select} one action (ReAct), while the deterministic strategy asks it to \\emph{rank} candidates for simulator evaluation. Both use identical system prompts and identical observation formatting.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex:8:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:57:Yes. We specify vLLM for inference, LoRA for fine-tuning, and provide all relevant configuration parameters (Table~\\ref{tab:hyperparams}). Model identifiers are given precisely (e.g., Qwen2.5-7B-Instruct, Qwen3-1.7B).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/responsibleNLPchecklist.tex:76:Yes. Claude (Anthropic) was used for code development, data analysis scripting, and manuscript drafting. All experimental design, scientific claims, and interpretation of results were conducted by the authors.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:29:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:64:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:8:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:12:[Omitted long matching line]",
    "numLines": 34
  },
  "sourceToolAssistantUUID": "f85f3215-af19-4877-99e2-ab5ba00d98bc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 47 · 2026-05-21T13:43:54.118Z_

<details><summary>↩ Tool result · `toolu_019f1UeX7Fd32GLTEYsfRgbM`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "51aab34a-9a56-465a-9791-0f62acb54a2e",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "33dedcc0-9725-41f3-a0a1-55b7a9bacded",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "51aab34a-9a56-465a-9791-0f62acb54a2e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 48 · 2026-05-21T13:43:55.069Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01H9HBuFXKPjg8pv5WCxvKoe`</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "33dedcc0-9725-41f3-a0a1-55b7a9bacded",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "79c4b961-aca5-413f-90d8-d5d3da25a3f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 49 · 2026-05-21T13:43:55.088Z_

<details><summary>↩ Tool result · `toolu_01H9HBuFXKPjg8pv5WCxvKoe`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "79c4b961-aca5-413f-90d8-d5d3da25a3f0",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "6d9086ba-6312-497b-9f88-f114bad84b66",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "79c4b961-aca5-413f-90d8-d5d3da25a3f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 50 · 2026-05-21T13:43:56.058Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01LLjSmJEEAcnZL1x2jwxgHG`</summary>

```json
{
  "pattern": "---",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6d9086ba-6312-497b-9f88-f114bad84b66",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "de3a6f91-a36c-4350-99f7-8e4dc20e96e0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-21T13:43:56.069Z_

<details><summary>↩ Tool result · `toolu_01LLjSmJEEAcnZL1x2jwxgHG`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:15:\citet{budget-aware-routing-2026} train episode-level routing policies under sparse terminal rewards---the closest setting to ours; they optimize \emph{which} model to invoke, whereas we diagnose \emph{what} drives the routing decision.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:18:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:78:We examine MATH and ALFWorld as boundary probes---not cross-domain validation---testing framework applicability across environments that instantiate ``deterministic computation'' differently (oracle simulator, code interpreter, admissible-action enumeration; see operationalization in \S\ref{sec:problem-setup}).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:82:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:107:Always-deterministic ($-9.47$) outperforms always-internal ($-39.07$) by 29.60 points. The oracle improves only to $-6.58$, with 96.3\% of decisions matching always-deterministic---an \emph{oracle degeneracy} where an always-deterministic lookup achieves 90.5\% of non-tie oracle decisions (balanced accuracy 50.0\%: perfect deterministic recall, zero internal recall).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:112:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:43:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:52:Our framework is diagnostic rather than prescriptive: it identifies what drives routing decisions but does not optimize the routing policy itself. Extending the counterfactual decomposition to prescribe optimal mixed-strategy routing---for example, by combining DAF analysis with online policy learning---is a natural next step.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:247:Exact permutation ($2{,}048$ perms) & $0.002$ & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:248:Sign test & $< 0.001$ & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:278:(none, full) & 245 & 78.9 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:426:Always-det & --- & --- & 50.0 \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:598:Qwen2.5-72B & ScienceWorld & 255 & 30.6\% & 2.75\% & +27.8 & 92.4\% & --- & death \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:600:Qwen2.5-7B & ALFWorld & 135 & 0\% & 0\% & 0 & 0\% & --- & info-asym \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:601:Llama-3.1-8B & ALFWorld & 135 & 0\% & 0\% & 0 & 0\% & --- & info-asym \\
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:777:Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\ref{tab:per-task}), indicating that excluded tasks are \emph{more} death-dominated than included tasks---the opposite of a cherry-picking bias.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:67:DAF (90.4\%) exceeds the label fraction (78.9\%) because death episodes carry disproportionately large score gaps ($P{=}100 \gg$ typical non-death $\Delta{\approx}29$), amplifying their weight in score-weighted aggregation. The label fraction---invariant to penalty magnitude---serves as the primary finding; DAF reflects the score-space reality under ScienceWorld's reward structure.
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:75:At step level, 97.4\% of oracle comparisons yield ties (\S\ref{sec:collection}); of 2{,}040 training steps, only 0.3\% exhibit strict directional conflict with episode labels, with 60.3\% pre-event neutral (neither strategy advantaged). Episode labels thus apply correct direction to uninformative steps---a granularity mismatch, not label error---explaining why step-level router training approaches chance performance (\S\ref{sec:router-diagnostic}).
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:4:In ScienceWorld \citep{scienceworld-2022}, a text-based science simulation, internal reasoning is error-prone---the model may hallucinate state changes (e.g., that water has boiled when the stove was never activated)---while deterministic external computation eliminates such errors via exact state transitions. The practical question: \emph{when should an agent route computation externally versus internally?}
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:6:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:15:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "de3a6f91-a36c-4350-99f7-8e4dc20e96e0",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "692313e4-ba2a-4ebd-8f3a-ac4a71048f66",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex:15:\\citet{budget-aware-routing-2026} train episode-level routing policies under sparse terminal rewards---the closest setting to ours; they optimize \\emph{which} model to invoke, whereas we diagnose \\emph{what} drives the routing decision.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:18:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:78:We examine MATH and ALFWorld as boundary probes---not cross-domain validation---testing framework applicability across environments that instantiate ``deterministic computation'' differently (oracle simulator, code interpreter, admissible-action enumeration; see operationalization in \\S\\ref{sec:problem-setup}).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:82:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:107:Always-deterministic ($-9.47$) outperforms always-internal ($-39.07$) by 29.60 points. The oracle improves only to $-6.58$, with 96.3\\% of decisions matching always-deterministic---an \\emph{oracle degeneracy} where an always-deterministic lookup achieves 90.5\\% of non-tie oracle decisions (balanced accuracy 50.0\\%: perfect deterministic recall, zero internal recall).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex:112:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:43:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:52:Our framework is diagnostic rather than prescriptive: it identifies what drives routing decisions but does not optimize the routing policy itself. Extending the counterfactual decomposition to prescribe optimal mixed-strategy routing---for example, by combining DAF analysis with online policy learning---is a natural next step.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:247:Exact permutation ($2{,}048$ perms) & $0.002$ & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:248:Sign test & $< 0.001$ & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:278:(none, full) & 245 & 78.9 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:426:Always-det & --- & --- & 50.0 \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:598:Qwen2.5-72B & ScienceWorld & 255 & 30.6\\% & 2.75\\% & +27.8 & 92.4\\% & --- & death \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:600:Qwen2.5-7B & ALFWorld & 135 & 0\\% & 0\\% & 0 & 0\\% & --- & info-asym \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:601:Llama-3.1-8B & ALFWorld & 135 & 0\\% & 0\\% & 0 & 0\\% & --- & info-asym \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:777:Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\\ref{tab:per-task}), indicating that excluded tasks are \\emph{more} death-dominated than included tasks---the opposite of a cherry-picking bias.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:67:DAF (90.4\\%) exceeds the label fraction (78.9\\%) because death episodes carry disproportionately large score gaps ($P{=}100 \\gg$ typical non-death $\\Delta{\\approx}29$), amplifying their weight in score-weighted aggregation. The label fraction---invariant to penalty magnitude---serves as the primary finding; DAF reflects the score-space reality under ScienceWorld's reward structure.\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex:75:At step level, 97.4\\% of oracle comparisons yield ties (\\S\\ref{sec:collection}); of 2{,}040 training steps, only 0.3\\% exhibit strict directional conflict with episode labels, with 60.3\\% pre-event neutral (neither strategy advantaged). Episode labels thus apply correct direction to uninformative steps---a granularity mismatch, not label error---explaining why step-level router training approaches chance performance (\\S\\ref{sec:router-diagnostic}).\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/abstract.tex:2:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:4:In ScienceWorld \\citep{scienceworld-2022}, a text-based science simulation, internal reasoning is error-prone---the model may hallucinate state changes (e.g., that water has boiled when the stove was never activated)---while deterministic external computation eliminates such errors via exact state transitions. The practical question: \\emph{when should an agent route computation externally versus internally?}\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:6:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex:15:[Omitted long matching line]",
    "numLines": 22
  },
  "sourceToolAssistantUUID": "de3a6f91-a36c-4350-99f7-8e4dc20e96e0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-21T13:43:57.946Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01A8e7vZzGeMJjspr1gtFBM8`</summary>

```json
{
  "pattern": "it is worth noting|notably|importantly|it should be noted",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
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
  "parentUuid": "692313e4-ba2a-4ebd-8f3a-ac4a71048f66",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "d559b5ef-335b-4986-b992-28157bb68e73",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 53 · 2026-05-21T13:43:57.960Z_

<details><summary>↩ Tool result · `toolu_01A8e7vZzGeMJjspr1gtFBM8`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:777:Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\ref{tab:per-task}), indicating that excluded tasks are \emph{more} death-dominated than included tasks---the opposite of a cherry-picking bias.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d559b5ef-335b-4986-b992-28157bb68e73",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "5e69e15c-734e-46e5-a586-c201126b80e4",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:777:Notably, the excluded-task aggregate DAF (0.991) exceeds the included-task DAF (0.904; Table~\\ref{tab:per-task}), indicating that excluded tasks are \\emph{more} death-dominated than included tasks---the opposite of a cherry-picking bias.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "d559b5ef-335b-4986-b992-28157bb68e73",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-21T13:43:58.892Z_

<details open><summary>🔧 Tool call — Grep · `toolu_014xUKf2GJ6e1oPLJwQXZUNV`</summary>

```json
{
  "pattern": "Furthermore|Moreover|Additionally",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5e69e15c-734e-46e5-a586-c201126b80e4",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "2fff853b-4f7b-4c79-88f2-b9bb99613666",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 55 · 2026-05-21T13:43:58.907Z_

<details><summary>↩ Tool result · `toolu_014xUKf2GJ6e1oPLJwQXZUNV`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2fff853b-4f7b-4c79-88f2-b9bb99613666",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "664bbdd5-2b44-45d2-9a27-bc4bf0204c72",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "2fff853b-4f7b-4c79-88f2-b9bb99613666",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 56 · 2026-05-21T13:44:00.353Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01AE9TUtBTYiJxLGq5ANsQ6d`</summary>

```json
{
  "pattern": "leverage|utilize|delve|myriad|plethora",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
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
  "parentUuid": "664bbdd5-2b44-45d2-9a27-bc4bf0204c72",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "e2d69a26-3c00-4cbb-876d-1ceae05034f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-21T13:44:00.368Z_

<details><summary>↩ Tool result · `toolu_01AE9TUtBTYiJxLGq5ANsQ6d`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:227:\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\ $\Delta_{\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e2d69a26-3c00-4cbb-876d-1ceae05034f0",
  "isSidechain": false,
  "promptId": "85579ddc-9b88-454b-a060-2515a0bb0362",
  "type": "user",
  "uuid": "0bbdf644-3c75-4064-84b5-cb79311f1d8e",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex:227:\\caption{Leave-one-out Pearson $r$ for the death rate differential vs.\\ $\\Delta_{\\text{full}}$ correlation. Full $r = 0.970$; LOO range $[0.963, 0.980]$. No single task type is a leverage point.}",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "e2d69a26-3c00-4cbb-876d-1ceae05034f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 58 · 2026-05-21T13:44:01.245Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Bi5v3ahJnELtQFAytLvrte`</summary>

```json
{
  "pattern": "ing,|ing\\.",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0bbdf644-3c75-4064-84b5-cb79311f1d8e",
  "isSidechain": false,
  "requestId": "req_011CbFp7ogKzLjtTaVrFbnd9",
  "type": "assistant",
  "uuid": "f85f3215-af19-4877-99e2-ab5ba00d98bc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T8NoCBbABMDk6AH71PuHct",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2119,
      "cache_creation_input_tokens": 37308,
      "cache_read_input_tokens": 49296,
      "output_tokens": 997,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37308,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2119,
          "output_tokens": 997,
          "cache_read_input_tokens": 49296,
          "cache_creation_input_tokens": 37308,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37308
          },
          "type": "message"
        }
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
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 15 warnin…",
  "leafUuid": "a67db42b-b9ea-43cd-aa78-bbbf82b25e1e",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 60_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Assistant

_source line 61 · 2026-05-21T13:47:20.613Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me count the LaTeX `---` (em-dash) occurrences more carefully. In LaTeX, `---` is an em-dash. Let me check how many there are in the main text (non-appendix) vs appendix, and identify specific locations.

Let me also check for `-ing` phrase endings and count Limitations section word count.

Let me now compile my findings systematically across all dimensions.

## 1. 叙事一致性分析

**Abstract 的问题**:
- Abstract says: "LLM agent routing---deciding when to rely on internal reasoning versus external tool use---is typically addressed by training routers directly, without first understanding what mechanistic signal drives the routing preference."


- The core issue is that there's no diagnostic approach established before constructing routers

**Intro 的问题**:
- Intro says: "when should an agent route computation externally versus internally?" and "The shared assumption---that routing signal stems from diverse sources and a learned router can exploit it---remains untested: no prior work has decomposed what drives routing decisions in interactive environments."
- Same fundamental gap: routing decisions haven't been decomposed or analyzed

These align well. ✓

**Intro 的贡献列表** vs **Method 实际做了什么**:
Contributions from Intro:
1. Episode-level counterfactual diagnostic framework (overcomes per-step oracle degeneracy,

Now I'm checking whether the contributions claimed in the intro match what the method actually delivers. The intro promises an episode-level counterfactual framework that decomposes routing signals and works from a small pilot, which maps to the counterfactual episode collection and episode-level labeling sections. The death avoidance finding (78.9%) with cross-model validation on Llama and Gemma, plus the cross-environment experiments on MATH and ALFWorld, all align with what's described in the method and experiments sections. The experiments validate the core claims well—death avoidance dominates routing decisions across models and environments, and a brief diagnostic pilot can identify this pattern before building a router. There's a slight tension though: the abstract frames the ~50-episode pilot as prospectively sufficient, but the validation is actually retrospective across four conditions. The title's framing around death avoidance as the dominant signal is well-supported, though I should note this retrospective validation caveat more carefully.

Looking at the cross-environment probes, there's a subtle narrative issue in how the contribution statement describes them. The MATH and ALFWorld experiments show the framework can diagnose different mechanisms—MATH finds no clear signal, ALFWorld identifies information asymmetry rather than death avoidance—which validates the framework's diagnostic utility. But calling this "robustness of the finding" is misleading, since the finding itself (death dominance) doesn't hold across these environments. The framework is robust; the specific finding is ScienceWorld-specific, which the paper actually handles correctly but the language could be clearer about.

Now checking the abstract structure: it covers the problem (routing preferences lack mechanistic understanding), method (counterfactual framework), results (death asymmetry explains 78.9% of labels, DAF achieves 88-90%, cross-environment validation), and significance (supports build-vs-buy decisions). The word count sits around 170, which is appropriate.

The introduction follows a compressed five-paragraph arc across roughly four sections: it opens with LLM agent routing context, identifies the gap in existing approaches (untested shared assumptions), presents the diagnostic framework and key findings, validates across environments, and lists contributions clearly. It's space-efficient but still covers the necessary ground.

For related work, the paper organizes discussion thematically using paragraph breaks across tool use, adaptive computation, counterfactual evaluation, and LLM agent environments.  Within the tool use section there's some listing of prior work—Toolformer, ToolACE, ToolkenGPT—but it's organized functionally rather than as a flat list. The positioning is sharp: acknowledging that existing work focuses on learning to use tools, then asking the prior question of what signal drives the routing decision itself.

Now I'm mapping contributions to their validation locations: the episode-level counterfactual diagnostic framework appears in method section 3 with experiments, plus a 50-episode pilot in the appendix; the 78.9% death asymmetry finding in ScienceWorld shows up in section 5.1, persists across interventions in 5.3, and holds across three model scales.

Cross-model validation lands in 5.2 and cross-environment in 5.4—all contributions have corresponding sections. The baselines and router training negative result in 5.5 and 5.6 aren't formally listed as contributions but serve as supporting evidence, which is fine. The title correctly scopes to ScienceWorld, and the abstract's claim about three model families checks out against the experiments.

Now I'm verifying the quantitative claims: the 78.9% figure comes directly from the data, the death-label fraction is penalty-independent by construction, and DAF consistently reaches 88–90% across Qwen, Llama, and Gemma. The 97.4% tie rate and the convergence pattern across model families all hold up. One potential overclaim is about the framework's generality—applying it to three environments is reasonable support for the framework itself, not necessarily the finding. I need to check whether the ≥12 pp residual gaps mentioned in the Discussion are actually verified in the experiments. I need to verify the gap calculations more carefully. The paper compares against a deterministic baseline of 16.3%, so retry at 43.5% gives a 27.2pp gap, Reflexion at 31.4% gives 15.1pp, and the 72B model at 30.6% gives 27.85pp against its own deterministic baseline of 2.75%. The action filtering approach sits around 29% with roughly a 9-14pp gap depending on the baseline. The ≥12pp claim across all four interventions checks out. Now looking at the experimental rigor—DAF reports a 95% confidence interval of 81.1% to 99.0%.

The cross-model DAF results include confidence intervals, and the router training metrics show mean and standard deviation across seeds. Per-task results are based on 20 episodes without individual error bars, though the authors acknowledge this as exploratory and underpowered. The baseline comparisons are solid, pulling from recent work through 2026 including toolformer, art, chameleon, retool, cogrouter, ares, and mtrouter, alongside standard agent improvement baselines like ReAct and Reflexion. The ablations cover the key method components—counterfactual labeling, DAF decomposition, and SCI—with capacity scaling experiments starting from 0.6B parameters.

For reproducibility, they're disclosing the hardware setup with 2 RTX 5090s and 4 RTX 6000 PROs, total training time around 200 GPU-hours, and hyperparameters in the appendix. Data preprocessing criteria are documented, code will be released upon acceptance, and they've included the responsible NLP checklist. The limitations section is thorough with five paragraphs addressing environmental scope, methodological constraints, statistical limitations, and diagnostic boundaries, plus an ethics statement.

Now I'm verifying that all the key mathematical symbols and terminology are used consistently throughout — things like δ for the death-rate differential, the various score gaps, and terms like "internal" versus "deterministic" are defined once and applied uniformly across the paper.

I'm catching a notation inconsistency though: the Method section defines δ as the death-rate differential, but the experimental tables use ΔDR for what appears to be the same quantity. I should flag this and make sure the notation is unified throughout.

Looking at the paper's structure, the transition from Method to Experiments flows naturally since the Method concludes with the scope of episode-level analysis and Experiments begins with the dataset. The Related Work placement after Experiments is unconventional for EMNLP but works here given the diagnostic nature of the work. The Discussion effectively explores why the router fails and the anatomy of failure rather than just restating results, though the Conclusion is quite brief.

For the Limitations section, I'm counting roughly 510 words across five distinct limitations—environmental scope, methodological constraints, statistical limitations, the pure-strategy upper bound, and diagnostic scope—which is substantial and substantive. The section honestly discusses specific ways the findings might not generalize.

Checking the writing style, I notice the paper uses LaTeX em-dashes extensively rather than Unicode em-dashes, and I should verify whether there are other stylistic markers that might feel too polished or AI-like. I'm going through the document systematically now, cataloging where em-dashes appear and checking whether they're being used appropriately as explanatory dashes. So far I've found instances in the abstract, introduction, and methods sections—things like "routing---deciding when" and "error-prone---the model may"—that all follow the explanatory pattern. I'm continuing to scan through the experiments section to get a complete picture of the em-dash usage across the main text. The em-dash frequency is genuinely high for academic writing, though many instances are legitimate parenthetical clarifications rather than stylistic flourishes. For the "-ing" phrases, most are participial constructions used as result clauses, which is standard in scientific papers but apparently flagged by the detector. Paragraph lengths look reasonable throughout, so that's not a concern.

Now checking abbreviations—Gemma-2-9B and the model names are all properly introduced with citations, which is fine. But I notice DAF (Death Avoidance Factor) gets defined in section 3.4 yet appears in the Abstract without the full form spelled out first, which violates the standard convention of introducing acronyms before use. LLM is standard enough for an EMNLP audience that defining it might be overkill, though I should flag it as a minor issue. I'm also noticing that the first contribution claims validated conditions, but the validation is retrospective—fitting thresholds to existing data rather than true prospective validation. That's a stronger claim than the evidence supports. Let me spot-check some of the key numbers: 78.9% matches the calculation from 75/95, the 245 episodes and 11 task types are consistent throughout, and I should verify the remaining statistics.

Now I'm verifying the model family counts and performance ranges. The DAF scores across models (Qwen 90.4%, Llama 88.2%, Gemma 89.7%) do fall within the stated 88–90% range, and the 97.4% tie rate checks out. The paper correctly refers to three model families even though it tests a 72B variant of Qwen, since that's still the same family. I'm also checking what the paper says about excluded cases.

Looking at the Discussion section, there's a mention of a 0.5B model showing a 13.3% death rate from a 15-episode pilot, but I can't find this data in the main experiments—it only appears in the Discussion and Appendix R. The sample size is quite small, so citing a specific percentage from just 15 episodes feels statistically weak, though the paper does acknowledge it as a pilot.

I'm also noticing the Related Work section comes after Experiments rather than in the more typical position after the Introduction. This is unconventional for NLP venues, though it can work for analysis-heavy papers where context from results helps frame the related work. Some reviewers might flag this as unusual.

Let me now pull together all my observations.

I should also verify the tables are using proper formatting — checking that they employ booktabs conventions rather than raw LaTeX lines. The tables look good with `\toprule`, `\midrule`, and `\bottomrule` throughout, no vertical lines or `\hline` commands. The paper also defines key terms like SCI (Signal Concentration Index) formally, and references like ReAct and Reflexion are properly cited. Now I'm compiling the full set of findings. The numbers check out across sections—Llama at 88.2%, Gemma at 89.7%, and Qwen at 90.4% all match between the abstract, introduction, and experiments. But I'm noticing a discrepancy in the limitations section where it mentions a 72B model achieving a 2.75% death rate, while the cross-model replication results show different magnitude variations across models despite consistent directional patterns.

There's also a subtle framing issue in the conclusion—when it says "cross-environment probes confirm generality," it's technically accurate because it's referring to the framework's ability to diagnose different mechanisms across environments, not claiming the death dominance finding itself is universal. MATH shows no signal and ALFWorld shows different signal, so the phrasing could be misread as overstating the generality of the finding rather than the framework. I should flag this as a potential clarity issue.

One more concern: the abstract claims the ~50-episode pilot "suffices to identify the dominant routing mechanism," but this is based on retrospective validation of 4 out of 4 conditions. The limitations section doesn't explicitly acknowledge that this sufficiency claim rests entirely on post-hoc validation rather than prospective evidence. I'll note this as a warning about the strength of the claim relative to the validation approach.

Now I'm going through the em-dash usage more systematically to get exact counts and distinguish between different contexts where they appear. Now I'm going through the remaining files to catalog the em-dash usage patterns. In experiments.tex, I'm seeing several double-dash constructions that serve as parenthetical asides—like "boundary probes---not cross-domain validation---testing" and "information asymmetry---not death avoidance---drives"—which are legitimate academic structures. The related_work and discussion sections have similar explanatory dashes that fit standard scholarly conventions rather than signaling AI-generated text.

Tallying everything up, I'm finding roughly 12-15 explanatory em-dashes across the main text, which is notably elevated for an 8-page paper where academic writing typically uses 0-3. I should also verify that key terms are properly introduced on first use—checking through the paper, I see that concepts like "counterfactual," "death asymmetry," "pure-strategy," "death-aware," "oracle degeneracy," and "signal concentration" are all either standard terminology or defined contextually where they appear.

The Responsible NLP Checklist is present and substantive. Now I'm reconsidering the Limitations section—it's currently running about 510 words across 5 paragraphs, but the user's guidance suggests keeping it brief at around 3 key points. That said, more thorough limitations generally strengthen a submission, so I'll leave it as is for now.

Looking at the page budget: the paper sits at 25 pages total with an 8-page main text limit for EMNLP 2026. Since limitations don't count toward that cap, I need to verify the core sections fit within the constraint.

Now checking whether the main results include proper uncertainty quantification—most do have confidence intervals or standard deviations reported, though Table 2 on agent improvement only shows point estimates rather than error bars despite having reasonable sample sizes.

I think I have what I need to write up the final audit report. Overall, the paper is well-executed and appropriately cautious in its claims, with the main issues being stylistic choices like em-dash usage and a few spots where the narrative could be clearer.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a67db42b-b9ea-43cd-aa78-bbbf82b25e1e",
  "isSidechain": false,
  "requestId": "req_011CbFp8srd2dDG1DRcjKocg",
  "type": "assistant",
  "uuid": "bf81fc39-3f4f-4b1e-8f45-b07225d5928f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019xTPsPRDVEd9LpEQkZbSm6",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8388,
      "cache_read_input_tokens": 86604,
      "output_tokens": 11557,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8388,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 11557,
          "cache_read_input_tokens": 86604,
          "cache_creation_input_tokens": 8388,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8388
          },
          "type": "message"
        }
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

_source line 62 · 2026-05-21T13:48:19.595Z_

```
[CONTENT_AUDIT_START]

### 叙事一致性（CRITICAL 级）

- [info] [叙事一致性] Abstract→Intro→Method→Experiments→Conclusion 主线高度一致：问题（routing signal 未被分解）、方法（episode-level counterfactual framework + DAF）、发现（78.9% death asymmetry）、意义（~50-episode pilot for build-vs-buy）全文贯穿，无明显漂移。
- [warning] [叙事一致性] introduction.tex:15 Contribution (3) 末尾写 "confirm the framework's diagnostic utility and the robustness of the finding"——MATH 无 signal、ALFWorld 是 info-asymmetry（非 death），它们只能证明 framework 的通用性，不能证明 "the finding"（death dominance）的 robustness。同一歧义出现在 conclusion.tex:3 "Cross-environment probes confirm generality"，读者可能误读为 death dominance 跨环境成立。建议拆成两句分别说 framework generality 和 ScienceWorld finding robustness（后者靠 cross-model）。
- [warning] [叙事一致性] abstract.tex:2 "A ~50-episode diagnostic pilot suffices to identify the dominant routing mechanism in a new environment" 和 introduction.tex:15 "validated 4/4 conditions"——该验证是 retrospective（同一研究的 4 个条件事后分类），非 prospective validation。Abstract 用 "suffices" 措辞偏强，Limitations 未专门标注此局限。建议 Abstract 加 "retrospectively validated" 或在 Limitations 增加一句。
- [warning] [叙事一致性] discussion.tex:8 "a 0.5B model shows reduced death rate (13.3%; n=15) because it is too weak to reach dangerous states, revealing an inverted-U capability-vulnerability relationship"——n=15 pilot（约 2 次 death）统计功效极低，"inverted-U relationship" 需要更多规模点支撑。当前仅有 0.5B/7-9B/72B 三个点，其中 0.5B 只是 pilot。建议降级为 "preliminary observation suggestive of an inverted-U pattern" 而非 "revealing"。

### 章节结构

- [info] [章节结构] Abstract 完整回答四个问题（问题、方法、结果、意义），~170 words，密度合适。
- [info] [章节结构] Introduction 遵循 背景→问题→gap→方法→贡献 结构，贡献列表清晰，每条有对应 section 引用。
- [info] [章节结构] Related Work 采用主题归纳式（Tool Use / Adaptive Computation / Counterfactual RL / Environments / Safe RL），positioning 清晰（"All focus on learning to use tools; we ask a prior question"）。Related Work 放在 Experiments 之后，对分析型论文合理但 EMNLP reviewer 可能不习惯。
- [info] [章节结构] Discussion 提供了超越 Results 数字的解读（router 失败原因分析、non-triviality 论证、practical implications），不是数字重复。

### 贡献-范围对齐

- [info] [贡献对齐] 3 条贡献均有对应 section/table：(1)→Method + §5.5 oracle degeneracy + Appendix R; (2)→§5.1 + §5.3; (3)→§5.2 + §5.4。无孤儿贡献。
- [info] [贡献对齐] §5.5 Baselines 和 §5.6 Router Training (negative result) 未列为 formal contribution 但作为支撑证据合理，无孤儿章节问题。
- [info] [贡献对齐] Title "A Counterfactual Analysis on ScienceWorld" 正确限定范围到 ScienceWorld，Abstract "across three model families" 与实验一致（Qwen/Llama/Gemma），"11 task types, 245 episodes" 全文一致。

### Claim 强度匹配

- [info] [claim强度] "78.9% of non-tie routing labels"（75/95）计算正确。"DAF reaches 88–90%"（88.2–90.4%）准确。"97.4% tie rate"（5935/6094）准确。核心定量 claim 与数据吻合。
- [info] [claim强度] claim 强度总体适当：单环境主结果用 "we find"，跨环境用 "boundary probes" 而非 "validation"，intervention 用 "suggestive evidence of a Reflexion ceiling"。Hedging 到位。
- [warning] [claim强度] discussion.tex:8 "revealing an inverted-U capability-vulnerability relationship"——如上所述，n=15 pilot 不足以 "reveal" 一个关系。应降级为 "suggestive of"。

### 实验严谨性

- [info] [实验严谨性] 主要结果附 95% CI（DAF bootstrap B=10000）和 cross-seed robustness。Router 训练报告 mean±std across 4-8 seeds。统计方法丰富（bootstrap, cluster bootstrap, wild cluster, permutation, sign test）。
- [info] [实验严谨性] Baseline 覆盖近期文献（2023-2026），包含 ReAct、Reflexion、10× scaling、action-space restriction 四种 intervention。
- [info] [实验严谨性] Ablation 与 Method 组件匹配：capacity scaling, text augmentation, leave-one-task-out, death-proximal labeling, reasoning depth, grounding ablation——数量充分。

### 可复现性披露

- [info] [可复现性] GPU（RTX 5090 + RTX 6000 PRO）、总 GPU-hours（~200h, 分三类细分）、hyperparams（Appendix Table）、vLLM 版本（v0.21.0）、temperature 设置均已披露。
- [info] [可复现性] Responsible NLP Checklist 实质填写（非全 N/A），Ethics Statement 覆盖数据/模型许可、计算资源。
- [info] [可复现性] Limitations 共 5 段 ~510 words，覆盖环境范围、方法限制、统计限制、pure-strategy 上界、diagnostic-only 限制。内容实质、非回避式。用户规则说 "只需要写一小段，覆盖 3 个点左右"——当前 5 段偏长，但 EMNLP 不计入 8 页限制，保留无害。

### 符号/术语一致性

- [warning] [符号一致性] Method §3.4 定义 $\delta = \mathbb{E}[d^{\tt int}] - \mathbb{E}[d^{\tt det}]$ 为 death-rate differential，但 Experiments 表格中用 $\Delta\text{DR}$ 表示同一量。两个符号指同一概念，应统一为一个（推荐统一用 $\delta$ 并在首次表格出现时标注 $\delta = \Delta\text{DR}$）。
- [info] [符号一致性] DAF、SCI、$\Delta_{\text{nd}}$、$\Delta_{\text{full}}$、$P$ 在全文定义后使用一致，无漂移。

### 章节过渡与逻辑流

- [info] [逻辑流] Method→Experiments 自然衔接（Method 定义工具，Experiments 应用到 ScienceWorld）。
- [info] [逻辑流] Discussion 不重复 Results 数字，而是提供机制解释（router 为何失败 = task-type-level signal）和 practical implications，符合规范。
- [info] [逻辑流] Conclusion 极简（2 句），覆盖核心发现和 framework generality。可以考虑增加 1 句 future direction 但非必须。

### Limitations 诚实度

- [info] [limitations] 5 段 ~510 words，≥5 个 distinct limitations，实质性讨论而非回避。满足所有审查标准。

### 去 AI 风格

- [warning] [去AI] 全文 LaTeX em-dash (---) 约 15+ 处用于解释性插入语，集中在 abstract.tex 和 introduction.tex。例：abstract.tex:2 "routing---deciding when to rely on..."、introduction.tex:4 "error-prone---the model may hallucinate..."、method.tex:67 "label fraction---invariant to penalty magnitude---serves as"。学术论文典型频率 0-3 处/篇，当前 15+ 处是 AI 写作的显著标志。建议逐一替换为逗号、括号或拆分句子。
- [info] [去AI] 无 Unicode em-dash（—）或解释性 en-dash（ – ）。
- [info] [去AI] main.tex:777 (appendix) 使用 "Notably"，是全文唯一一处 filler word，位于 appendix 中，影响较小。
- [info] [去AI] 无 "Furthermore"/"Moreover"/"Additionally" 连续使用，无 "delve"/"leverage"/"utilize"/"myriad"/"plethora"。
- [info] [去AI] 段落长度合理，无过度分段（2-3 句一段）问题。
- [info] [去AI] 存在少量 -ing 分词结果从句（如 "...confirming that...", "...explaining why..."），频率不高，在学术写作中可接受。

[CONTENT_AUDIT_END]
```

**审计总结**：叙事主线高度一致，无 critical 级问题。主要修复项：(1) 全文 ~15 处 LaTeX em-dash 应大幅削减（最显著的 AI 风格标志）；(2) Conclusion/Abstract 中 "cross-environment probes confirm generality" 表述需明确区分 framework generality 和 finding robustness；(3) ~50-episode pilot "suffices" 应标注为 retrospective validation；(4) Discussion 中 0.5B inverted-U claim 应降级为 preliminary observation；(5) $\delta$ vs $\Delta\text{DR}$ 符号应统一。

[AUDIT_DONE]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bf81fc39-3f4f-4b1e-8f45-b07225d5928f",
  "isSidechain": false,
  "requestId": "req_011CbFp8srd2dDG1DRcjKocg",
  "type": "assistant",
  "uuid": "6bbd3a75-5207-4b78-8d1e-fef2d96a8d50",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/.claude/sessions/paper_audit_content_6813a604",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019xTPsPRDVEd9LpEQkZbSm6",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8388,
      "cache_read_input_tokens": 86604,
      "output_tokens": 11557,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8388,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 11557,
          "cache_read_input_tokens": 86604,
          "cache_creation_input_tokens": 8388,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8388
          },
          "type": "message"
        }
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

_source line 63_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 15 warnin…",
  "leafUuid": "6bbd3a75-5207-4b78-8d1e-fef2d96a8d50",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 64_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 65_

```json
{
  "type": "last-prompt",
  "lastPrompt": "项目：simgate-modular-routing Venue：emnlp-2026 论文目录：/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper  Phase 1 确定性检查结果： 源码检查: passed=True, 0 critical, 15 warnin…",
  "leafUuid": "6bbd3a75-5207-4b78-8d1e-fef2d96a8d50",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

### Runtime record

_source line 66_

```json
{
  "type": "ai-title",
  "aiTitle": "Content structure audit for SimGate modular routing paper",
  "sessionId": "6d9a8d29-6528-42b3-9f02-c9d1618fc7dd"
}
```

---

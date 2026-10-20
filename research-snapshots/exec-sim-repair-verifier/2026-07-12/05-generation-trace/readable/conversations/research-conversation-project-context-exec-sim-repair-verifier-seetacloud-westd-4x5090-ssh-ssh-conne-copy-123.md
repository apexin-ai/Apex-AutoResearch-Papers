# Research conversation: <project_context> # 项目: exec-sim-repair-verifier ## 运行环境 - 服务器名: seetacloud-westd-4x5090 - SSH 连接命令: ssh connect.westd.s

**A Systematic Comparison of Execution-Free Verification Formulations for Code Repair (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 47
- **Recorded user turns:** 1
- **Tool calls:** 11
- **Original source:** `logs/chats/exported-trajectories/account-1/f2fe2b10-7f45-45b0-92d7-5ac890a91bc1.jsonl`
- **Structured JSON:** [`2b912ba928614d08d462.json`](../../sessions/2b/2b912ba928614d08d462.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-21T15:15:00.838Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-21T15:15:00.838Z",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "content": "&lt;project_context>\n# 项目: exec-sim-repair-verifier\n\n## 运行环境\n- 服务器名: seetacloud-westd-4x5090\n- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /home/sonny/exec-sim-repair-verifier\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n扫描 appendix.tex，检查残留问题。\n\n**任务**：\n1. 读 appendix.tex：Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex`\n2. 读主文件了解上下文：\n   - Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex`\n   - Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/experiments.tex`\n   - Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/conclusion.tex`\n\n**检查项**：\n1. **残留 placeholder 措辞**：搜索 \"preliminary\", \"in progress\", \"TBD\", \"TODO\", \"placeholder\", \"to be\", \"forthcoming\", \\tbd{} 等\n2. **与主文不一致的数字或表述**：\n   - 主文说 19-26pp gap → appendix 中引用的 gap 数字是否一致？\n   - 主文说 z=-23.7 → appendix 中的统计数字？\n   - 主文说 oracle 90.63%/95.83% → appendix 中？\n   - 主文说 217× → appendix 中？\n   - 主文说 ~370 GPU-hours → appendix 中？\n   - 主文说 TOST p=0.007 → appendix 中？\n3. **可以删除或精简的冗余段落**：与主文重复的描述、过度详细的证明\n\n**产出**：写入 `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/appendix_cleanup_report.md`\n\n**格式**：\n```markdown\n# Appendix Cleanup Scan Report\n\n## 1. Placeholder/Tentative Wording\n| Line | Current Text | Issue | Suggested Fix |\n|------|-------------|-------|---------------|\n\n## 2. Inconsistencies with Main Text\n| Item | Main Text Value | Appendix Value | Line | Fix |\n|------|----------------|----------------|------|-----|\n\n## 3. Redundancy / Pruning Opportunities\n| Section | Lines | Issue | Recommendation |\n|---------|-------|-------|----------------|\n\n## Summary\n[总体评估 + 优先级排序]\n```\n\n**注意**：不直接修改 tex 文件，只产出报告。"
}
````

---

### Runtime record

_source line 2 · 2026-05-21T15:15:00.845Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-21T15:15:00.845Z",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

## Round 1

45 recorded events

### User

_source line 3 · 2026-05-21T15:15:00.898Z_

&lt;project_context>
# 项目: exec-sim-repair-verifier

## 运行环境
- 服务器名: seetacloud-westd-4x5090
- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /home/sonny/exec-sim-repair-verifier


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
扫描 appendix.tex，检查残留问题。

**任务**：
1. 读 appendix.tex：Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex`
2. 读主文件了解上下文：
   - Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex`
   - Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/experiments.tex`
   - Read `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/conclusion.tex`

**检查项**：
1. **残留 placeholder 措辞**：搜索 "preliminary", "in progress", "TBD", "TODO", "placeholder", "to be", "forthcoming", \tbd{} 等
2. **与主文不一致的数字或表述**：
   - 主文说 19-26pp gap → appendix 中引用的 gap 数字是否一致？
   - 主文说 z=-23.7 → appendix 中的统计数字？
   - 主文说 oracle 90.63%/95.83% → appendix 中？
   - 主文说 217× → appendix 中？
   - 主文说 ~370 GPU-hours → appendix 中？
   - 主文说 TOST p=0.007 → appendix 中？
3. **可以删除或精简的冗余段落**：与主文重复的描述、过度详细的证明

**产出**：写入 `/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/appendix_cleanup_report.md`

**格式**：
```markdown
# Appendix Cleanup Scan Report

## 1. Placeholder/Tentative Wording
| Line | Current Text | Issue | Suggested Fix |
|------|-------------|-------|---------------|

## 2. Inconsistencies with Main Text
| Item | Main Text Value | Appendix Value | Line | Fix |
|------|----------------|----------------|------|-----|

## 3. Redundancy / Pruning Opportunities
| Section | Lines | Issue | Recommendation |
|---------|-------|-------|----------------|

## Summary
[总体评估 + 优先级排序]
```

**注意**：不直接修改 tex 文件，只产出报告。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "9d34f137-1741-4fbe-b8c9-2feab23426b5",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-21T15:15:00.897Z_

```json
{
  "parentUuid": "9d34f137-1741-4fbe-b8c9-2feab23426b5",
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
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file"
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
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "674d4be5-5c83-4826-b447-56f7989cf4a0",
  "timestamp": "2026-05-21T15:15:00.897Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-21T15:15:00.898Z_

```json
{
  "parentUuid": "674d4be5-5c83-4826-b447-56f7989cf4a0",
  "isSidechain": false,
  "attachment": {
    "type": "agent_listing_delta",
    "addedTypes": [
      "claude",
      "Explore",
      "general-purpose",
      "Plan",
      "statusline-setup"
    ],
    "addedLines": [
      "- claude: Catch-all for any task that doesn't fit a more specific agent. FleetView's default when no agent name is typed. (Tools: *)",
      "- Explore: Fast read-only search agent for locating code. Use it to find files by pattern (eg. \"src/components/**/*.tsx\"), grep for symbols or keywords (eg. \"API endpoints\"), or answer \"where is X defined / which files reference Y.\" Do NOT use it for code review, design-doc auditing, cross-file consistency checks, or open-ended analysis — it reads excerpts rather than whole files and will miss content past its read window. When calling, specify search breadth: \"quick\" for a single targeted lookup, \"medium\" for moderate exploration, or \"very thorough\" to search across multiple locations and naming conventions. (Tools: All tools except Agent, ExitPlanMode, Edit, Write, NotebookEdit)",
      "- general-purpose: General-purpose agent for researching complex questions, searching for code, and executing multi-step tasks. When you are searching for a keyword or file and are not confident that you will find the right match in the first few tries use this agent to perform the search for you. (Tools: *)",
      "- Plan: Software architect agent for designing implementation plans. Use this when you need to plan the implementation strategy for a task. Returns step-by-step plans, identifies critical files, and considers architectural trade-offs. (Tools: All tools except Agent, ExitPlanMode, Edit, Write, NotebookEdit)",
      "- statusline-setup: Use this agent to configure the user's Claude Code status line setting. (Tools: Read, Edit)"
    ],
    "removedTypes": [],
    "isInitial": true,
    "showConcurrencyNote": true
  },
  "type": "attachment",
  "uuid": "70183754-de6a-4e4a-b9f4-f7a97107a62d",
  "timestamp": "2026-05-21T15:15:00.898Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 6 · 2026-05-21T15:15:00.898Z_

```json
{
  "parentUuid": "70183754-de6a-4e4a-b9f4-f7a97107a62d",
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
  "uuid": "af69d05d-417e-430d-80a6-0eba6271b918",
  "timestamp": "2026-05-21T15:15:00.898Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 7 · 2026-05-21T15:15:00.898Z_

```json
{
  "parentUuid": "af69d05d-417e-430d-80a6-0eba6271b918",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "b669802c-4543-4b52-9d01-387e1a10cbde",
  "timestamp": "2026-05-21T15:15:00.898Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 8_

```json
{
  "type": "ai-title",
  "aiTitle": "Scan appendix.tex for residual issues",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Assistant

_source line 9 · 2026-05-21T15:15:04.355Z_

<details><summary>Logged reasoning block</summary>

```text
Let me read all the required files in parallel first.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b669802c-4543-4b52-9d01-387e1a10cbde",
  "isSidechain": false,
  "requestId": "req_011CbFw5LBrLTbgAZViyq7fK",
  "type": "assistant",
  "uuid": "3337a34a-6059-4e08-a2a3-21521c8031f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011DoB1jz7aNEmrxedrFHCwQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13336,
      "cache_read_input_tokens": 11447,
      "output_tokens": 337,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 337,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 13336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13336
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-21T15:15:04.924Z_

<details open><summary>🔧 Tool call — Read · `toolu_015e8JEuvPXbjvYYqggbBDpv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3337a34a-6059-4e08-a2a3-21521c8031f0",
  "isSidechain": false,
  "requestId": "req_011CbFw5LBrLTbgAZViyq7fK",
  "type": "assistant",
  "uuid": "89ab2aac-b481-47ea-a6ab-83dcca8575c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011DoB1jz7aNEmrxedrFHCwQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13336,
      "cache_read_input_tokens": 11447,
      "output_tokens": 337,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 337,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 13336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13336
          },
          "type": "message"
        }
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

_source line 11 · 2026-05-21T15:15:05.418Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JCZgqSMkXjga26Z3fhHita`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "89ab2aac-b481-47ea-a6ab-83dcca8575c1",
  "isSidechain": false,
  "requestId": "req_011CbFw5LBrLTbgAZViyq7fK",
  "type": "assistant",
  "uuid": "e320c838-a663-4e7c-a5b8-68350f2ea649",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011DoB1jz7aNEmrxedrFHCwQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13336,
      "cache_read_input_tokens": 11447,
      "output_tokens": 337,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 337,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 13336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13336
          },
          "type": "message"
        }
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

_source line 12 · 2026-05-21T15:15:06.453Z_

<details><summary>↩ Tool result · `toolu_01Av4PdgKj3ayrHpgtbZNJm7`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We presented the first systematic comparison of three execution-free verification formulations (\cls{}, \cwm{}, \traj{}). At function level, \cls{} and \cwm{} are statistically equivalent (TOST $p{=}0.007$, 5 seeds); \traj{} reaches parity on Qwen3 but not DeepSeek-Coder (2.69\pp{}). Per-test classification achieves 217$\times$ higher throughput while providing diagnostic signal whose downstream utility remains unconfirmed ($n{=}44$, $p{=}0.42$). Complementary errors (oracle: 90.63\%/95.83\%; single-seed) motivate complexity-aware routing. At repository level under ${\leq}$8B LoRA fine-tuning, a robust interaction ($z{=}-23.7$) confirms divergence (19--26\pp{}, single-seed variant-level), with \cwm{} falling below majority baseline---consistent across families but dependent on multiple confounds (\S\ref{sec:threats}). \cls{} is recommended for throughput; behavior at larger scale remains open~\cite{meta2025cwm}.
5	
6	\section*{Limitations}
7	
8	Most repo-level comparisons use limited seeds; the gap (19--26\pp{}) exceeds any single assessed confound (\S\ref{sec:threats}), but correlated confounds mean definitive causal attribution requires multi-seed replication. Our \cwm{} baseline uses ${\leq}$8B LoRA fine-tuning, not the original 32B CWM with execution trace mid-training~\cite{meta2025cwm}; at larger scale, the generation bottleneck may diminish. Training data comprises synthetic mutations~\cite{andrews2005mutation,just2014mutants}; the synthetic-to-real transfer gap for absolute accuracy remains untested, though the coupling effect supports relative ranking validity (Appendix~\ref{app:limitations}). Model coverage is limited to 6--8B code-specialized LLMs; generalization to larger or general-purpose models is untested. All code, data, and model checkpoints will be released upon acceptance.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dfaaf263-d95b-475c-8c06-83c27f0556df",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "2905a3ad-5728-44a2-a0a6-9f0a9259aad3",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe presented the first systematic comparison of three execution-free verification formulations (\\cls{}, \\cwm{}, \\traj{}). At function level, \\cls{} and \\cwm{} are statistically equivalent (TOST $p{=}0.007$, 5 seeds); \\traj{} reaches parity on Qwen3 but not DeepSeek-Coder (2.69\\pp{}). Per-test classification achieves 217$\\times$ higher throughput while providing diagnostic signal whose downstream utility remains unconfirmed ($n{=}44$, $p{=}0.42$). Complementary errors (oracle: 90.63\\%/95.83\\%; single-seed) motivate complexity-aware routing. At repository level under ${\\leq}$8B LoRA fine-tuning, a robust interaction ($z{=}-23.7$) confirms divergence (19--26\\pp{}, single-seed variant-level), with \\cwm{} falling below majority baseline---consistent across families but dependent on multiple confounds (\\S\\ref{sec:threats}). \\cls{} is recommended for throughput; behavior at larger scale remains open~\\cite{meta2025cwm}.\n\n\\section*{Limitations}\n\nMost repo-level comparisons use limited seeds; the gap (19--26\\pp{}) exceeds any single assessed confound (\\S\\ref{sec:threats}), but correlated confounds mean definitive causal attribution requires multi-seed replication. Our \\cwm{} baseline uses ${\\leq}$8B LoRA fine-tuning, not the original 32B CWM with execution trace mid-training~\\cite{meta2025cwm}; at larger scale, the generation bottleneck may diminish. Training data comprises synthetic mutations~\\cite{andrews2005mutation,just2014mutants}; the synthetic-to-real transfer gap for absolute accuracy remains untested, though the coupling effect supports relative ranking validity (Appendix~\\ref{app:limitations}). Model coverage is limited to 6--8B code-specialized LLMs; generalization to larger or general-purpose models is untested. All code, data, and model checkpoints will be released upon acceptance.",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "dfaaf263-d95b-475c-8c06-83c27f0556df",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-21T15:15:05.614Z_

<details><summary>↩ Tool result · `toolu_015e8JEuvPXbjvYYqggbBDpv`</summary>

```text
1	\appendix
2	
3	\section{Oracle Accuracy-Utility Analysis}
4	\label{app:oracle}
5	
6	We stratify SWE-bench Verified instances by F2P test count $T$, comparing per-test vs.\ trajectory-level oracle resolve rates under i.i.d.\ and block-correlated error models (ICC $= 0.191$, from function-level analysis; \S\ref{sec:equivalence}).
7	
8	\begin{table}[h]
9	\centering
10	\small
11	\caption{Oracle accuracy-utility frontier: per-test advantage stratified by F2P test count ($T$) on SWE-bench Verified (500 instances). Block-correlated model uses function-level ICC $= 0.191$ (from function-level analysis, \S\ref{sec:equivalence}). P2P regression rate: 1.04\% mean, 0\% median.}
12	\label{tab:oracle}
13	\resizebox{\columnwidth}{!}{%
14	\setlength{\tabcolsep}{3pt}
15	\begin{tabular}{lcccc}
16	\toprule
17	\textbf{$T$} & \textbf{Inst.\%} & \textbf{i.i.d.\ (\pp{})} & \textbf{Block (\pp{})} & \textbf{Contrib.\%} \\
18	\midrule
19	$1$ & 68.7 & $-$0.04 & $-$0.09 & $\approx$0 \\
20	$2$ & 19.1 & 18.49 & 31.69 & 55.3 \\
21	$3$--$5$ & 7.1 & 25.00 & 40.74 & $\approx$26 \\
22	$\geq 6$ & 5.1 & 30.00 & 40.06 & $\approx$19 \\
23	\midrule
24	\textbf{All} & 100.0 & --- & \textbf{10.93} & 100.0 \\
25	\bottomrule
26	\end{tabular}}
27	\end{table}
28	
29	\begin{figure}[h]
30	\centering
31	\includegraphics[width=\columnwidth]{figures/paper/fig3_oracle_stratified.pdf}
32	\caption{Oracle per-test advantage by F2P test count $T$. Advantage is zero at $T{=}1$ (68.7\%) and concentrates at $T{=}2$ (19.1\%, contributing 55.3\% of total advantage).}
33	\label{fig:oracle_stratified}
34	\end{figure}
35	
36	Table~\ref{tab:oracle} and Figure~\ref{fig:oracle_stratified} reveal a sharp concentration: at $T = 1$ (68.7\% of instances), per-test and trajectory-level are informationally equivalent. The advantage materializes at $T = 2$ (19.1\%), where block-correlated advantage reaches 31.69\pp{} (55.3\% of total). The overall block-correlated advantage is 10.93\pp{}, driven by the $T \geq 2$ minority. Block correlation amplifies relative to i.i.d.: at $T = 2$, 31.69\pp{} vs.\ 18.49\pp{} (1.7$\times$). P2P regression is negligible (1.04\% mean, 0\% median); the practical value concentrates in F2P discrimination.
37	
38	\paragraph{Sensitivity to ICC estimate.}
39	The analysis above uses ICC $= 0.191$ from function-level analysis (\S\ref{sec:equivalence}), where mean cluster size $\bar{k} \approx 16.5$ yields DEFF $= 3.97$. At repository level, within-problem correlation is substantially stronger: ICC $= 0.3146$ with DEFF $= 114.4$ (\S\ref{sec:repo}), a consequence of the larger and more heterogeneous test suites in SWE-bench Verified problems. Under higher ICC, within-problem errors cluster more tightly and amplify the block-correlated per-test advantage at each $T$ stratum; the correction from i.i.d.\ to block-correlated grows monotonically with ICC. The function-level ICC $= 0.191$ used in Table~\ref{tab:oracle} thus provides a conservative lower bound on the per-test advantage. The repo-level correlation structure would yield an even larger gap between per-test and trajectory-level oracle resolve rates, which strengthens the case for per-test granularity at repository-level complexity.
40	
41	\section{Ablation Studies}
42	\label{app:ablations}
43	
44	\paragraph{LoRA rank sensitivity.}
45	All \cwm{} experiments use LoRA rank $r{=}16$. To test whether this capacity constraint handicaps \cwm{}, we train rank-32 variants (seed 42), doubling adapter parameters.
46	
47	\begin{table}[h]
48	\centering
49	\small
50	\caption{LoRA rank ablation for \cwm{} 4B (seed 42, 3 epochs, lr $= 2{\times}10^{-4}$). Rank-16 seed variance: 0.53\pp{} (seeds 42 vs.\ 456).}
51	\label{tab:rank_ablation}
52	\setlength{\tabcolsep}{4pt}
53	\begin{tabular}{lccccc}
54	\toprule
55	\textbf{Config} & \textbf{$\alpha/r$} & \textbf{Acc (\%)} & \textbf{Fail \fone{}} & \textbf{Pass \fone{}} & \textbf{$\Delta$} \\
56	\midrule
57	$r{=}16$, $\alpha{=}32$ & 2 & \textbf{87.51} & --- & --- & --- \\
58	$r{=}32$, $\alpha{=}32$ & 1 & 87.00 & 87.1 & 86.9 & $-$0.51 \\
59	$r{=}32$, $\alpha{=}64$ & 2 & 87.04 & 87.27 & 86.79 & $-$0.47 \\
60	\bottomrule
61	\end{tabular}
62	\end{table}
63	
64	Both rank-32 variants fall within the 2-seed variance of the rank-16 baseline (0.53\pp{} between seeds 42 and 456). The $\alpha{=}64$ variant (matching the baseline $\alpha/r{=}2$ ratio) rules out the confound that the $\alpha{=}32$ result might reflect reduced effective scaling rather than rank insensitivity. This is consistent with \cwm{}'s function-level performance being bounded by output-format constraints rather than adapter capacity.
65	
66	\paragraph{Majority voting.}
67	Majority voting ($K{=}3$) decreases accuracy from 87.51\% to 86.83\% ($-$0.68\pp{}): errors are systematic rather than stochastic, so sampling-based ensembles do not help.\footnote{These majority-voting values were computed from an unverified checkpoint and may differ slightly from the val-best checkpoint results.}
68	
69	\paragraph{Sequence-length ablation details.}
70	Both formulations are trained with \texttt{max\_seq\_length}$=$2,048. At inference, \cwm{} reserves \texttt{max\_new\_tokens}$=$512, leaving ${\sim}$1,536 effective input tokens; \cls{} allocates nearly all context to input (5,120--8,192 tokens). A matched-context ablation (\cls{} 8B at 2,048 tokens) achieves 83.04\%, only 1.44\pp{} below the 8,192-token evaluation (84.48\%), though truncation introduces 136 unparseable outputs (1.39\% of test samples). The matched-context gap (\cls{}@2,048 vs.\ \cwm{}@2,048) is 25.00\pp{} (98\% of the full 25.59\pp{} gap), confirming that input context disparity explains at most 3\% of the difference.
71	
72	\paragraph{Training data size control.}
73	\label{app:downsample}
74	To control for the training set size asymmetry between \cls{} (${\sim}$70K instances) and \traj{} (386 variant-level instances, ${\sim}$8K per-test equivalents, at repo level), we downsample \cls{} training data to match \traj{} in data volume. Downsampled \cls{} (Qwen3-4B, seed 42) achieves 80.74\% repo-level per-test accuracy, only 2.89\pp{} below the full-data \cls{} (83.63\%) and still 7.82\pp{} above \traj{} (72.92\%). The \cls{} formulation advantage is not attributable to training data volume.
75	
76	\paragraph{Few-shot prompting baselines.}
77	\label{app:few_shot}
78	We evaluate 3-shot in-context learning at repo level to test whether prompting strategy closes the gap to fine-tuned models. Table~\ref{tab:few_shot} reports both per-test and variant-level accuracy.
79	
80	\begin{table}[h]
81	\centering
82	\small
83	\caption{Repo-level prompting baselines (per-test $n{=}9{,}784$; variant-level $n{=}48$). Majority baseline: 72.96\% per-test, 54.17\% variant-level.}
84	\label{tab:few_shot}
85	\setlength{\tabcolsep}{4pt}
86	\resizebox{\columnwidth}{!}{%
87	\begin{tabular}{lcccc}
88	\toprule
89	\textbf{Model} & \textbf{0-shot (per-test)} & \textbf{3-shot (per-test)} & \textbf{3-shot (variant)} \\
90	\midrule
91	Qwen3-8B & 49.90\% & 71.61\% & 45.83\%\textsuperscript{$\ast$} \\
92	DeepSeek-6.7B & 48.54\% & 46.28\% & 45.83\%\textsuperscript{$\ast$} \\
93	\bottomrule
94	\end{tabular}}
95	
96	\vspace{2pt}
97	{\footnotesize \textsuperscript{$\ast$}Both models achieve 45.83\% by correctly classifying all 22 unresolved variants and zero resolved variants (22/48 = 45.83\%), equivalent to an always-predict-unresolved baseline. The 100\% overlap in variant-level predictions confirms complete degradation at task-relevant granularity.}
98	\end{table}
99	
100	Both models converge to exactly 45.83\% variant-level accuracy under 3-shot prompting, below majority baseline (54.17\%). Variant-level analysis reveals this is not a coincidence: both models correctly classify all 22 unresolved variants and zero resolved variants, equivalent to an always-predict-unresolved baseline with 100\% prediction overlap. Per-test accuracy diverges sharply (Qwen3-8B 71.61\% vs.\ DeepSeek 46.28\%), but this divergence is entirely superficial: Qwen3-8B predicts pass on nearly all tests, inflating per-test accuracy on a pass-heavy dataset (72.96\% pass rate) without genuine discriminative ability. Per-test metrics can thus severely misrepresent baseline capability; variant-level evaluation is necessary to detect complete degradation. Neither 0-shot nor few-shot prompting approaches fine-tuned performance (82--84\% per-test); fine-tuning is a necessary condition for repo-level verification.
101	
102	\section{Repo-Level Per-Mutation Breakdown}
103	\label{app:repo_mutation}
104	
105	Table~\ref{tab:mutation_breakdown} compares per-mutation accuracy at repo level. \cls{} produces 0\% unparseable outputs; all values are direct classification accuracy. \cwm{} overall accuracy includes default-pass assignment for unparseable outputs (see \S\ref{sec:repo}).
106	
107	\begin{table}[h]
108	\centering
109	\small
110	\caption{Per-mutation test accuracy (\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \cls{} 8B reports two seeds; $\Delta$ is mean 4B$\to$8B gain for \cls{}. \cwm{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\%, parseable acc 23.5\%).}
111	\label{tab:mutation_breakdown}
112	\resizebox{\columnwidth}{!}{%
113	\setlength{\tabcolsep}{3pt}
114	\begin{tabular}{lccccccc}
115	\toprule
116	\textbf{Mutation} & \textbf{$n$} & \textbf{CLS 4B} & \textbf{CLS 8B s42} & \textbf{CLS 8B s123} & \textbf{CWM 4B} & \textbf{CWM 8B} & \textbf{$\Delta$ CLS} \\
117	\midrule
118	gold & 4,633 & 98.25 & 96.24 & 99.60 & 66.72 & 80.06 & $-$0.33 \\
119	operator\_swap & 3,357 & 78.91 & 81.38 & 82.60 & --- & 54.57 & +3.08 \\
120	off\_by\_one & 183 & 58.47 & 86.89 & 79.20 & --- & 63.39 & \textbf{+24.58} \\
121	return\_value & 562 & 67.97 & 75.44 & 66.40 & --- & 49.11 & +2.95 \\
122	boundary\_removal & 1,049 & 46.90 & 46.90 & 44.90 & --- & 42.23 & $-$1.00 \\
123	\bottomrule
124	\end{tabular}}
125	\end{table}
126	
127	Table~\ref{tab:cwm_mutation_parse} shows that \cwm{} generation quality degrades from 4B to 8B across all mutation types.
128	
129	\begin{table}[h]
130	\centering
131	\small
132	\caption{\cwm{} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\%) for gold at both scales.}
133	\label{tab:cwm_mutation_parse}
134	\setlength{\tabcolsep}{4pt}
135	\begin{tabular}{lcccc}
136	\toprule
137	& \multicolumn{2}{c}{\textbf{Parse Rate (\%)}} & \multicolumn{2}{c}{\textbf{Parse Acc (\%)}} \\
138	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
139	\textbf{Mutation} & \textbf{4B} & \textbf{8B} & \textbf{4B} & \textbf{8B} \\
140	\midrule
141	gold & 43.5 & 23.9 & 23.5 & 16.5 \\
142	operator\_swap & 56.9 & 21.2 & 63.1 & 58.8 \\
143	off\_by\_one & 4.4 & 27.3 & 0.0 & 38.0 \\
144	return\_value & 48.8 & 26.9 & 27.0 & 56.9 \\
145	boundary\_removal & 30.6 & 51.8 & 59.2 & 51.8 \\
146	\bottomrule
147	\end{tabular}
148	\end{table}
149	
150	Key findings: (1)~Gold parse rate collapses from 43.5\% to 23.9\% at 8B; the simplest generation target (unmodified code, where all tests pass) degrades most, consistent with a fundamental generation bottleneck rather than task difficulty. (2)~Among parseable outputs, gold accuracy is 16.5--23.5\%: the model generates outputs that fail exact-match even for correct code. (3)~\texttt{off\_by\_one} is an anomaly: parse rate \emph{increases} from 4.4\% to 27.3\%, but this is from an extremely low base ($n{=}8$ parseable at 4B), making both directions unreliable for this category.
151	
152	\section{Variant-Level Accuracy}
153	\label{app:variant_level}
154	
155	Table~\ref{tab:variant_level} reports variant-level accuracy ($n{=}48$) alongside per-test accuracy for all repo-level configurations. For \cls{}, the aggregation penalty (per-test $\to$ variant-level drop) ranges from 1\pp{} to 19\pp{} and is largest for models with low fail recall under the all-pass rule. \cwm{} variant-level accuracy (48--52\%) falls at or below the majority baseline, consistent with format collapse as the dominant failure mode.
156	
157	\begin{table}[h]
158	\centering
159	\small
160	\caption{Repo-level per-test vs.\ variant-level accuracy ($n{=}48$ variants). Penalty = per-test $-$ variant-level. \traj{} predicts variant outcomes directly (no aggregation). Variant-level majority baseline: 54.17\% (26/48).}
161	\label{tab:variant_level}
162	\setlength{\tabcolsep}{3pt}
163	\resizebox{\columnwidth}{!}{%
164	\begin{tabular}{llcccc}
165	\toprule
166	\textbf{Model} & \textbf{Seed} & \textbf{Per-test (\%)} & \textbf{Variant (\%)} & \textbf{Penalty (\pp{})} & \textbf{Fail Recall (\%)} \\
167	\midrule
168	\multicolumn{6}{l}{\emph{\cls{}}} \\
169	Qwen3-8B & s42 & 84.48 & 72.92 & 11.56 & 56.76 \\
170	Qwen3-8B & s123 & 85.60 & 81.25 & 4.35 & 51.44 \\
171	Qwen3-4B & s42 & 83.63 & 64.58 & 19.05 & 48.72 \\
172	DeepSeek-6.7B & s42 (e1) & 82.61 & 81.25 & 1.36 & 51.02 \\
173	DeepSeek-6.7B & s42 (e3) & 82.51 & 79.17 & 3.34 & 38.47 \\
174	DeepSeek-6.7B & s123 & 74.93 & 56.25 & 18.68 & ${\sim}$13.72 \\
175	\midrule
176	\multicolumn{6}{l}{\emph{\cwm{}}} \\
177	Qwen3-8B & s42 & 65.17 & 52.08 & 13.09 & --- \\
178	DeepSeek-6.7B$^\dagger$ & s123 & --- & 47.92 & --- & --- \\
179	\midrule
180	\multicolumn{6}{l}{\emph{\traj{}}} \\
181	Qwen3-4B & s42 & --- & 72.92 & --- & --- \\
182	Qwen3-8B & s42 & --- & 70.83 & --- & --- \\
183	DeepSeek-6.7B & 3-seed & --- & 77.08 $\pm$ 3.61 & --- & --- \\
184	\midrule
185	Majority & --- & 72.96 & 54.17 & --- & --- \\
186	\bottomrule
187	\end{tabular}}
188	\vspace{2pt}
189	
190	{\footnotesize $^\dagger$Evaluated on ${\sim}$75\% of test instances (7210--7668 of 9784). DeepSeek \traj{} Table~\ref{tab:repo_level} reports 3 seeds (42/123/456) for alignment with \cls{}/\cwm{} seed coverage; three supplementary seeds (0/789/999) yield 75.0\%, 66.7\%, 79.2\% respectively (6-seed mean 75.35 $\pm$ 5.00\%), consistent in direction.}
191	\end{table}
192	
193	\section{Training Hyperparameters}
194	\label{app:hyperparams}
195	
196	Table~\ref{tab:hyperparams} lists all hyperparameters used for fine-tuning. Both \cls{} and \cwm{} share the same LoRA configuration, optimizer, and training schedule; the only differences are per-device batch size, gradient accumulation steps (adjusted to maintain identical effective batch size of 32 across model sizes), and learning rate (DeepSeek-Coder uses $2{\times}10^{-4}$ vs.\ $5{\times}10^{-5}$ for Qwen3, selected via grid search over $\{5{\times}10^{-5}, 1{\times}10^{-4}, 2{\times}10^{-4}\}$ on held-out validation loss).
197	
198	\begin{table}[h]
199	\centering
200	\small
201	\caption{Training hyperparameters for \cls{}/\cwm{} configurations. \traj{} models use lr $= 2{\times}10^{-4}$ due to the smaller training set (${\sim}$8K function-level instances vs.\ ${\sim}$70K for \cls{}/\cwm{}); other hyperparameters are shared.}
202	\label{tab:hyperparams}
203	\resizebox{\columnwidth}{!}{%
204	\begin{tabular}{ll}
205	\toprule
206	\multicolumn{2}{l}{\textbf{Shared across all configurations}} \\
207	\midrule
208	LoRA rank / alpha / dropout & 16 / 32 / 0.05 \\
209	LoRA targets & \texttt{q/k/v/o\_proj} \\
210	Optimizer & AdamW ($\beta_1{=}0.9$, $\beta_2{=}0.999$) \\
211	LR scheduler & Linear \\
212	Effective batch size & 32 \\
213	Max sequence length & 2,048 \\
214	Epochs & 3 \\
215	Precision & bf16 \\
216	Gradient checkpointing & \checkmark \\
217	Seeds (function) & \{42, 123, 456, 789, 0\}\textsuperscript{$b$} \\
218	Seeds (repo) & \{42, 123, 456\}\textsuperscript{$c$} \\
219	\bottomrule
220	\end{tabular}}
221	
222	\vspace{6pt}
223	
224	\resizebox{\columnwidth}{!}{%
225	\begin{tabular}{lccc}
226	\toprule
227	\multicolumn{4}{l}{\textbf{Model-family--specific parameters}} \\
228	\midrule
229	& \textbf{Qwen3-4B} & \textbf{Qwen3-8B} & \textbf{DS-6.7B} \\
230	\midrule
231	Learning rate & 5e-5 & 5e-5 & 2e-4 \\
232	Weight decay & 0.01 & 0.01 & 0.0 \\
233	Warmup ratio & 0.05 & 0.05 & 0.1 \\
234	Batch / grad.\ accum.\ (\cls{}) & 2 / 16 & 1 / 32 & 2 / 16 \\
235	Batch / grad.\ accum.\ (\cwm{}) & 1 / 32 & 1 / 32 & 1 / 32 \\
236	Training samples & 70,748 & 70,748 & 67,343--70,748\textsuperscript{$a$} \\
237	\bottomrule
238	\end{tabular}}
239	
240	\vspace{2pt}
241	{\footnotesize $^a$DeepSeek \cls{} canonical run (s42) uses drop preprocessing, which excludes 3,405 sequences exceeding max length (67,343 of 70,748). The s123 run uses truncate preprocessing (70,748 samples) but produces NaN validation loss. See \S\ref{sec:setup}. $^b$Seeds 789 and 0 use NF4 quantization; others use bf16. $^c$Repo-level seed coverage varies by configuration; see Table~\ref{tab:repo_level} caption for per-model counts.}
242	\end{table}
243	
244	\paragraph{Data processing.} DeepSeek CWM seeds use \texttt{train\_unified.py}, which drops samples exceeding \texttt{max\_seq\_length} (3{,}405 of 70{,}748 samples, 4.8\%). Qwen CWM seeds use \texttt{train\_repo\_cwm.py}, which truncates and retains all samples. This difference affects total training steps (${\sim}$12{,}627 vs.\ ${\sim}$13{,}266 for DeepSeek, ${\sim}$6{,}633 for Qwen) but not the training data distribution, as dropped samples are uniformly distributed across labels.
245	
246	\paragraph{Prompt templates.} Prompt templates for all formulations (\cls{}, \cwm{}, \traj{}) are provided in the code repository. \cls{} uses a binary classification template (``Does this test pass or fail?''); \cwm{} uses an execution simulation template (``What is the output of this test?''); \traj{} uses a variant-level verdict template (``Is this patch resolved or unresolved?'').
247	
248	\paragraph{Mutation operators.} We use five mutation types: (1)~\emph{gold}: unmodified code (all tests pass); (2)~\emph{operator\_swap}: replaces comparison or arithmetic operators (e.g., \texttt{<} $\to$ \texttt{<=}); (3)~\emph{off\_by\_one}: shifts loop bounds or array indices by $\pm$1; (4)~\emph{return\_value}: modifies return statements (e.g., negating a boolean, changing a constant); (5)~\emph{boundary\_removal}: removes conditional guards or boundary checks. Mutation operators were applied using AST-level transformation; variants that did not alter any test outcome were discarded.
249	
250	\paragraph{Compute budget.}
251	All experiments were conducted on NVIDIA RTX 5090 GPUs. Training time is approximately 1.5 hours per run for 4B models and 2 hours for 8B models. Total compute budget: ${\sim}$370 GPU-hours across 223 completed runs (135 successful, 88 failed/killed; ${\sim}$46 unique configurations including seeds, formulations, model sizes, and ablations).
252	
253	\section{Val-Test Mutation Type Distribution}
254	\label{app:mutation_distribution}
255	
256	Table~\ref{tab:mutation_distribution} reports the mutation type composition of the repo-level validation and test sets. The most notable shift is \texttt{operator\_swap}, which nearly doubles from val (19.1\%) to test (34.3\%), while \texttt{off\_by\_one} shrinks from 10.0\% to 1.9\%.
257	
258	\begin{table}[h]
259	\centering
260	\small
261	\caption{Repo-level mutation type distribution: validation vs.\ test set, with per-type \cls{} accuracy at two model sizes (seed 42). Shift = test\% $-$ val\%.}
262	\label{tab:mutation_distribution}
263	\setlength{\tabcolsep}{3pt}
264	\resizebox{\columnwidth}{!}{%
265	\begin{tabular}{lccccc}
266	\toprule
267	\textbf{Mutation Type} & \textbf{Val (\%)} & \textbf{Test (\%)} & \textbf{Shift} & \textbf{\cls{} 4B} & \textbf{\cls{} 8B} \\
268	\midrule
269	gold & 45.2 & 47.4 & +2.2 & 98.3 & 96.2 \\
270	operator\_swap & 19.1 & 34.3 & +15.2 & 78.9 & 81.4 \\
271	boundary\_removal & 15.0 & 10.7 & $-$4.3 & 46.9 & 46.9 \\
272	return\_value & 10.7 & 5.7 & $-$5.0 & 68.0 & 75.4 \\
273	off\_by\_one & 10.0 & 1.9 & $-$8.1 & 58.5 & 86.9 \\
274	\bottomrule
275	\end{tabular}}
276	\end{table}
277	
278	The \texttt{operator\_swap} shift is the primary source of val-test distribution mismatch. Since \cls{} achieves moderate accuracy on this type (78.9--81.4\%), the over-representation in the test set does not systematically bias overall accuracy estimates in either direction. Two boundary observations are notable: (1)~\texttt{boundary\_removal} represents a scale-invariant difficulty ceiling at ${\sim}$47\% across both model sizes: this mutation type resists capacity scaling; (2)~\texttt{off\_by\_one} shows the largest scaling gain (+28.4\pp{}, 58.5\%$\to$86.9\%) but its small test share (1.9\%) limits its contribution to overall accuracy differences across scales.
279	
280	\section{Qualitative Error Analysis}
281	\label{app:qualitative}
282	
283	To complement the quantitative divergence reported in \S\ref{sec:repo}, we examine representative errors from each formulation at repository level.
284	
285	\paragraph{\cwm{} failure modes.}
286	Two patterns account for the majority of unparseable \cwm{} outputs on Qwen3. (1)~\emph{Task misunderstanding}: the model generates a complete simulated test runner log (test names, timing, summary lines) rather than a pass/fail verdict. For instance, on \texttt{django\_\_django-14315}, the model outputs a fabricated 1,248-token Django test execution trace with hallucinated test names that do not exist in the target file. The model confuses ``predict test outcome'' with ``simulate test execution environment.'' (2)~\emph{Autoregressive degeneration}: the model enters a repetitive loop (e.g., repeating \texttt{from \_pytest.config import \_parse\_pytest\_args} until truncation at 4,542 tokens). Both patterns produce zero usable signal and default to the majority-class label. This explains why unparseable predictions carry higher accuracy than parseable ones (\S\ref{sec:repo}).
287	
288	\paragraph{\cls{} failure modes.}
289	\cls{} errors concentrate in two categories requiring multi-step reasoning. False positives arise from \emph{cross-concern value propagation}: a boundary removal mutation in \texttt{pytest} converts a guarded attribute access (\texttt{if xfailed and not xfailed.run}) to \texttt{if True:}, causing a NoneType error on tests exercising unrelated skip marks. The model fails to trace the None path through the pytest hook lifecycle. False negatives arise from \emph{mathematical equivalence}: on \texttt{HumanEval/130} (Tribonacci variant), the model predicts failure for correct code because verifying the self-referential recurrence requires algebraic substitution rather than syntactic inspection. This single problem accounts for 17\% of all function-level false negatives.
290	
291	\paragraph{Complementarity.}
292	These failure patterns operate at different levels: \cwm{} fails at the format level (producing no usable signal), while \cls{} fails at the reasoning level (producing a confident but incorrect binary verdict). Both formulations are FP-dominant (over-predict failure), but \cwm{}'s higher FP rate (70.3\% vs.\ 56.5\%) means it over-predicts failure on instances \cls{} correctly classifies, producing partial complementarity (oracle combination: 90.63\%; \S\ref{app:extended_analysis}, paragraph a).
293	
294	\section{Extended Analysis}
295	\label{app:extended_analysis}
296	
297	\paragraph{(a) Error complementarity.}
298	\cls{} and \cwm{} are both FP-dominant at function level but at different rates, producing partial complementarity. Among \cls{} errors (seed 42), 56.5\% are false positives (PASS $\to$ FAIL); among \cwm{} errors, 70.3\% are false positives. Both formulations over-predict failure, but \cwm{}'s stronger FP bias means it incorrectly rejects passing tests that \cls{} correctly accepts. An oracle combination achieves 90.63\% accuracy (1713/1890 correct, 177 both-wrong; +2.80\pp{} over the best single formulation, \cls{} 87.83\%; single-seed estimate, seed 42). The complementarity arises from different \emph{degrees} of fail-bias rather than opposite error directions: \cwm{}'s generation bottleneck produces aggressive failure predictions, while \cls{}'s single-token output is more calibrated. Ensemble approaches exploiting this degree difference are a natural direction.
299	
300	\paragraph{(b) CWM error mode breakdown.}
301	Among unparseable \cwm{} outputs (Qwen3, repo-level), 76.9\% contain no execution keywords; 22.9\% contain ambiguous co-occurring pass/fail keywords. Format compliance varies sharply across repositories (scikit-learn: near-zero unparseable; sphinx: 100\%); repository-specific code patterns interact with the model's generation capabilities in complex ways. This per-repository variation is consistent with a model/tokenizer-specific failure rather than a formulation-level one.
302	
303	\paragraph{(c) Relaxed matching does not rescue \cwm{}.}
304	Relaxed matching (tolerating format deviations, L0--L4) \emph{decreases} \cwm{} accuracy: 58.04\%$\to$56.98\% (seed 42) and 59.09\%$\to$55.91\% (seed 123). Unparseable predictions default to the majority class (pass, 72.96\%), which outperforms the model's own parseable predictions (42--53\%). The divergence widens from 26\pp{} to 28\pp{} under relaxed matching. This rules out the hypothesis that parsing strictness inflates the observed gap. Constrained decoding~\cite{willard2023outlines} could enforce format compliance but would not address the semantic accuracy deficit among parseable outputs.
305	
306	\paragraph{(d) Variance compression.}
307	\cwm{}'s 5-seed standard deviation (0.37\pp{}) is lower than \cls{} (0.78\pp{}) and \traj{} (0.97\pp{}) at function level. If \cwm{} performance is capped by output-format constraints at a given complexity level, seed-to-seed variability is compressed relative to formulations whose performance depends more on learned representations.
308	
309	\paragraph{(e) Per-test precision and recall.}
310	\cls{} achieves fail \fone{} 87.59\% (precision 86.20\%, recall 89.04\%) at seed 42.% derived from overlap analysis (error_overlap_matched_seed.json); FP=130, FN=100, TP=848, TN=812
311	Multi-F2P instances (6--10 tests) reach 96.3\% accuracy, consistent with the oracle finding that per-test granularity is most valuable for complex instances.
312	
313	\paragraph{(f) Block correlation.}
314	Within-problem errors are correlated (ICC $= 0.191$, DEFF $= 3.97$, 2.81$\times$ more all-correct problems than i.i.d.\ expectation). All statistical tests use clustered bootstrap accordingly.
315	
316	\paragraph{(g) Failed interventions.}
317	We systematically tested four interventions targeting different hypothesized causes of \cwm{} repo-level degradation; all failed:
318	
319	\begin{itemize}[leftmargin=*,itemsep=1pt,topsep=2pt]
320	\item \textbf{Capacity (rank 32):} Doubling adapter parameters does not improve accuracy ($-$0.51\pp{}, within seed variance; Appendix~\ref{app:ablations}).
321	\item \textbf{Majority voting ($K{=}3$):} Accuracy \emph{decreases} by 0.68\pp{} (87.51\%$\to$86.83\%); 93.3\% of samples are unanimous across passes, and net flips are negative ($-$13), indicating errors are systematic bias rather than stochastic noise.
322	\item \textbf{Relaxed matching (L0--L4):} Tolerating format deviations \emph{decreases} accuracy from 58.04\% to 56.98\% (seed 42; Appendix~\ref{app:extended_analysis}(c)), because unparseable predictions default to the majority class (pass, 72.96\%), which outperforms the model's own parseable predictions (38--43\%).
323	\item \textbf{Model scaling (4B$\to$8B):} Parseable-only accuracy decreases (42.88\%$\to$38.52\%) while unparseable rate increases (53.7\%$\to$73.8\%); the apparent accuracy gain is entirely a default-assignment artifact (\S\ref{sec:repo}).
324	\end{itemize}
325	
326	\noindent Each intervention targets a distinct alternative explanation (insufficient capacity, random noise, parsing strictness, model scale); the uniform failure across all four confirms the bottleneck is formulation-level---output space complexity at repo level exceeds what ${\leq}$8B generation models can handle, independent of these surface-level factors.
327	
328	\paragraph{(h) Per-mutation scaling patterns.}
329	Scaling benefits are highly non-uniform across mutation types (Table~\ref{tab:mutation_breakdown}). \texttt{off\_by\_one} shows the largest \cls{} scaling gain: 58.5\% (4B) to 86.9\% (8B, $+$28.4\pp{}). In contrast, \texttt{boundary\_removal} is scale-invariant at ${\sim}$47\% across both sizes, which marks an intrinsic difficulty ceiling. For \cwm{}, gold mutation parse rate collapses from 43.5\% (4B) to 23.9\% (8B) despite being the simplest target: generation capability degrades even for trivially correct code at larger scale within Qwen3. The val-test mutation type distribution differs notably (\texttt{operator\_swap} shifts from 19.1\% to 34.3\%; Table~\ref{tab:mutation_distribution}), but this shift does not systematically bias overall accuracy because \cls{} performance on \texttt{operator\_swap} (78.9--81.4\%) is close to the overall mean.
330	
331	\paragraph{(i) Inference efficiency.}
332	\cls{} achieves 217$\times$ higher throughput than \cwm{} at repo level (853 vs.\ 3.9 inferences/min; Qwen3-4B, RTX 5090, 100 samples, avg ${\sim}$1,040 input tokens). The speedup derives directly from the formulation: classification requires a single output token, whereas \cwm{} generates an average of 477 tokens per inference. Median latency is 48ms (\cls{}) vs.\ 16.3s (\cwm{}). At the observed unparseable rate of 73.8\% (8B), the majority of \cwm{}'s generation budget produces tokens that cannot yield a valid verdict. This \cls{}--\cwm{} efficiency gap is an inherent property of the formulation difference (1 vs.\ $O(L)$ output tokens) and should generalize across models, unlike the accuracy divergence which may be model-contingent.
333	
334	The \cls{}--\traj{} efficiency comparison is more nuanced, because \cls{} makes one call per test while \traj{} makes one call per instance. Per-call, \cls{} is 20--138$\times$ faster (depending on input length: 47ms for short contexts vs.\ 2,632ms for \traj{}). However, the per-instance effective speedup depends on test count $|T|$: at function level ($|T| \approx 2.3$), \cls{} is ${\sim}$24$\times$ faster (108ms vs.\ 2,632ms per instance); at repo level ($|T| \approx 12.3$, ${\sim}$70ms/call with longer inputs), \cls{} is ${\sim}$3$\times$ faster (861ms vs.\ 2,631ms). A crossover exists at $|T| \approx 50$ tests, beyond which \traj{}'s single-call amortization dominates. This boundary condition is informative for deployment: \cls{} is strongly preferred for function-level and moderate repo-level test suites, while extremely large test suites ($>$50 tests per instance) favor trajectory-level efficiency despite its coarser diagnostic signal.
335	
336	\paragraph{(j) Re-repair pilot.}
337	We tested whether per-test diagnostic feedback improves downstream repair. A Qwen3-8B repair agent received either per-test diagnostic signals (which specific tests failed and why) or binary accept/reject feedback, evaluated on 44 SWE-bench Verified instances. The diagnostic condition achieved accuracy no higher than the binary baseline ($A_1 = 52.3\%$, $p = 0.42$, effect size $\approx 0$). Per-test diagnostic information does not automatically translate to repair improvements at this scale. The negative result may reflect insufficient agent capability to exploit fine-grained feedback, insufficient sample size (at $n = 44$, statistical power is ${\sim}$0.3 for a medium effect size), or a genuine limitation of the diagnostic-to-repair translation.
338	
339	\section{TOST Margin Sensitivity}
340	\label{app:tost_sensitivity}
341	
342	Table~\ref{tab:tost_sensitivity} reports the TOST equivalence $p$-value as a function of the equivalence margin, computed on the 5-seed variant-level \cls{}--\traj{} comparison (gap $= -$0.45\pp{}, 523 variants, 114 clusters, clustered bootstrap).
343	
344	\begin{table}[h]
345	\centering
346	\small
347	\caption{TOST margin sensitivity for \cls{}--\traj{} variant-level equivalence (5 seeds, 523 variants, 114 clusters). The smallest margin achieving equivalence at $\alpha = 0.05$ is $\pm$1.52\pp{}.}
348	\label{tab:tost_sensitivity}
349	\setlength{\tabcolsep}{4pt}
350	\begin{tabular}{ccc}
351	\toprule
352	\textbf{Margin ($\pm$\pp{})} & \textbf{$p$-value} & \textbf{Equivalent ($\alpha{=}0.05$)?} \\
353	\midrule
354	1.0 & $\gg$0.05 & No \\
355	1.5 & 0.054 & No (borderline) \\
356	\textbf{1.52} & ${\sim}$\textbf{0.05} & \textbf{Smallest margin} \\
357	1.71 & 0.027 & Yes \\
358	2.0 & 0.007 & Yes \\
359	3.0 & $4.6{\times}10^{-5}$ & Yes \\
360	5.0 & $\ll$0.001 & Yes \\
361	\bottomrule
362	\end{tabular}
363	\end{table}
364	
365	The minimum equivalence margin is $\pm$1.52\pp{}, 0.48\pp{} below our pre-specified $\pm$2\pp{} threshold. The $\pm$2\pp{} threshold was set based on deployment relevance rather than observed data: at function-level accuracy (85--88\%), a 2\pp{} per-test difference corresponds to ${\sim}$38 additional errors across 1,890 tests (${\sim}$2--3 problems out of 114), comparable in magnitude to between-seed standard deviation (0.37--0.97\pp{}) and checkpoint selection noise ($<$1\pp{}). Differences within this range do not reliably distinguish formulations from training noise in pipeline selection decisions.
366	
367	
368	\section{Variant-Level Effect Sizes}
369	\label{app:power}
370	
371	Table~\ref{tab:variant_power} reports variant-level bootstrap confidence intervals for the repo-level formulation comparisons ($n{=}48$ variants). Following Hoenig and Heisey~\cite{hoenig2001}, we report minimum detectable effect (MDE) rather than post-hoc observed power.
372	
373	\begin{table}[h]
374	\centering
375	\small
376	\caption{Variant-level bootstrap analysis ($n{=}48$). \cls{}--\cwm{} uses paired bootstrap (same variants, same seed); \cls{}--\traj{} uses unpaired bootstrap (per-variant \traj{} predictions not archived for pairing). MDE at $n{=}48$: ${\sim}$25\pp{}.}
377	\label{tab:variant_power}
378	\setlength{\tabcolsep}{3pt}
379	\resizebox{\columnwidth}{!}{%
380	\begin{tabular}{llccc}
381	\toprule
382	\textbf{Comparison} & \textbf{Config} & \textbf{$\Delta$ (\pp{})} & \textbf{95\% CI} & \textbf{$p$} \\
383	\midrule
384	\multicolumn{5}{l}{\emph{\cls{} vs.\ \cwm{} (paired)}} \\
385	& Qwen3-8B & +29.17 & [10.42, 47.92] & 0.003 \\
386	& DeepSeek-6.7B & +35.42 & [18.75, 50.05] & ${<}$0.001 \\
387	\midrule
388	\multicolumn{5}{l}{\emph{\cls{} vs.\ \traj{} (unpaired)}} \\
389	& Qwen3-4B & $-$4.17 & wide & 0.740 \\
390	& Qwen3-8B & +8.33 & wide & 0.385 \\
391	& DeepSeek-6.7B & 0.00 & wide & 1.000 \\
392	\bottomrule
393	\end{tabular}}
394	\end{table}
395	
396	At $n{=}48$, the MDE is ${\sim}$25\pp{}. The \cls{}--\cwm{} gap (29--35\pp{}) exceeds this threshold, confirming that $n{=}48$ is sufficient to detect the observed divergence. The \cls{}--\traj{} gaps ($<$10\pp{}) fall well below the MDE: any true difference is too small to detect at this sample size, consistent with the function-level TOST equivalence (\S\ref{sec:equivalence}).
397	
398	The \cls{}--\traj{} unpaired bootstrap produces wider confidence intervals than paired analysis would; \traj{} per-variant predictions were not archived in a format that permits pairing. The \cls{}--\cwm{} paired comparison uses \cls{} s123 vs.\ \cwm{} s42 (different seeds), but the CI lower bound of 10.42\pp{} far exceeds the seed noise observed in function-level experiments ($<$2\pp{}).
399	
400	
401	\section{Multiple Comparison Correction}
402	\label{app:holm}
403	
404	Table~\ref{tab:holm} applies Holm-Bonferroni correction~\cite{holm1979} to the four primary statistical comparisons across this study ($k{=}4$, family-wise $\alpha{=}0.05$).
405	
406	\begin{table}[h]
407	\centering
408	\small
409	\caption{Holm-Bonferroni correction for primary comparisons ($k{=}4$). Comparisons ranked by raw $p$-value; each tested against $\alpha / (k - \text{rank} + 1)$.}
410	\label{tab:holm}
411	\setlength{\tabcolsep}{3pt}
412	\resizebox{\columnwidth}{!}{%
413	\begin{tabular}{clcccc}
414	\toprule
415	\textbf{Rank} & \textbf{Comparison} & \textbf{Raw $p$} & \textbf{Factor} & \textbf{Adj $p$} & \textbf{Sig.?} \\
416	\midrule
417	1 & Repo: \cls{} vs \cwm{} & 0.003 & $\times$4 & 0.012 & \checkmark \\
418	2 & Func: \cls{} vs \traj{} (TOST $\pm$2\pp{}) & 0.0071 & $\times$3 & 0.021 & \checkmark \\
419	3 & Repo: \cwm{} vs \traj{} & 0.039 & $\times$2 & 0.078 & --- \\
420	4 & Repo: \cls{} vs \traj{} & 0.385 & $\times$1 & 0.385 & --- \\
421	\bottomrule
422	\end{tabular}}
423	\end{table}
424	
425	The two core claims survive correction: the repo-level \cls{}--\cwm{} gap (adjusted $p{=}0.012$) and function-level \cls{}--\traj{} equivalence (adjusted $p{=}0.021$). The repo-level \cwm{}--\traj{} comparison does not survive correction (adjusted $p{=}0.078$); we interpret this difference as directionally consistent but not confirmatory.
426	
427	\section{Mixed-Effects Regression}
428	\label{app:interaction}
429	
430	We fit mixed-effects linear probability models (LPM) to test the formulation$\times$complexity interaction formally. We choose LPM because coefficients are directly interpretable as probability differences (percentage points), consistent with the reporting units in the main text; at these sample sizes ($n{\approx}56$K cross-complexity, repo-level pooled cross-model) and base rate range (0.6--0.9), LPM and logistic regression yield identical significance conclusions~\cite{angrist2009mostly}.
431	
432	\paragraph{Cross-complexity model (DeepSeek-Coder).} \texttt{correct $\sim$ formulation $\times$ complexity + (1|problem\_id)}, $n{=}56{,}480$ observations (\cls{} + \cwm{} $\times$ function + repo), 139 problem clusters. The \cwm{} main effect at function level is non-significant ($\hat{\beta}{=}-0.002$, $z{=}-0.25$, $p{=}0.805$); the \cwm{}$\times$repo interaction is highly significant ($\hat{\beta}{=}-0.219$, $z{=}-23.7$, $p{<}0.001$). \cwm{} and \cls{} are statistically indistinguishable at function level ($\Delta{=}-0.2$\pp{}, $p{=}0.805$) but diverge by 22\pp{} at repo level, confirming the complexity-dependent divergence is not an artifact of aggregation.
433	
434	\paragraph{Repo-level cross-model model.} \texttt{correct $\sim$ formulation $\times$ model + (1|problem\_id)}, both model families, repo level only. \cwm{} deficit: $\hat{\beta}{=}-0.22$ ($-$22\pp{}, $z{=}-64.4$, $p{<}0.001$). Model effect: +1.1\pp{} for Qwen3 ($z{=}3.1$, $p{=}0.002$). Formulation$\times$model interaction: +1.6\pp{} less \cwm{} degradation on Qwen3 ($z{=}2.8$, $p{=}0.006$). Formulation explains $>$95\% of the predictable variance; model identity modulates gap magnitude without changing direction. The 25-cluster random intercept structure limits effective degrees of freedom for the random effects; inferences on fixed effects (formulation, complexity) are robust as they pool across the full observation count.
435	
436	\section{CWM Parseable Bias Analysis}
437	\label{app:parseable_bias}
438	
439	The default-to-pass assignment for unparseable \cwm{} outputs is not random with respect to instance difficulty. Unparseable instances have significantly higher pass rates than parseable ones (74.6\% vs.\ 68.3\%, $\chi^2$ $p = 5.9 \times 10^{-10}$), and \cls{} models achieve higher accuracy on unparseable instances (86.4\% vs.\ 79.1\%, $p = 3.3 \times 10^{-18}$). This indicates that \cwm{}'s parsing failures concentrate on simpler, pass-heavy instances where the majority-class default happens to be correct more often. Cross-model Jaccard overlap of unparseable instance sets is 0.46, confirming this pattern is instance-driven (specific inputs consistently cause parsing failure across models) rather than stochastic. The net effect is that \cwm{}'s reported accuracy is inflated by default-correct assignments on easy instances, while its effective discriminative accuracy on harder instances is substantially lower than the aggregate figure suggests.
440	
441	
442	\section{Threats to Validity (Full Analysis)}
443	\label{app:threats}
444	
445	We identify five potential confounds and assess their impact on our conclusions.
446	
447	\paragraph{Checkpoint selection.} Val-based selection is unavailable for runs with NaN validation loss (all \cwm{} repo-level runs, DeepSeek \cls{} s123), which default to the final epoch checkpoint. A checkpoint ablation on Qwen3-8B \cls{} s42 quantifies this confound: epoch~1 (ckpt-2200) achieves 85.34\%, val-selected (ckpt-3600) 84.48\%, and final epoch (ckpt-6633) 85.29\%---a $<$1\pp{} range. The val-selected checkpoint is the lowest, indicating no upward bias from checkpoint selection. The Qwen3-8B \traj{} comparison (epoch 2: 72.92\% vs.\ epoch 3: 70.83\%) shows a slightly larger ${\sim}$2\pp{} shift.
448	
449	\paragraph{Evaluation sequence length.} \cwm{} accuracy varies by ${\sim}$9\pp{} across evaluation sequence lengths for the same checkpoint (seq2048: ${\sim}$65\% vs.\ seq4096: ${\sim}$56\%), driven by unparseable-rate differences that propagate through majority-class default assignment. \cls{} is invariant to this parameter. Cross-model \cwm{} comparisons use different eval lengths (Qwen3: 8192, DeepSeek: 4096) and are not directly comparable in absolute terms. A matched-sequence evaluation shows ${\sim}$1.5\pp{} difference for \cls{} (Appendix~\ref{app:ablations}), insufficient to explain the 19--26\pp{} gap. Furthermore, increasing Qwen3-8B \cwm{} evaluation from seq4096 to seq8192 \emph{raises} the unparseable rate (63.7\%$\to$74\%) while changing accuracy by only 0.81\pp{} (64.36\%$\to$65.17\%); giving the model more generation budget worsens format compliance rather than improving it, confirming that format collapse is a structural bottleneck rather than a truncation artifact. Practitioners must standardize evaluation sequence length for generation-based formulations.
450	
451	\paragraph{Preprocessing.} DeepSeek \cls{} accuracy ranges from 82.61\% (s42, drop preprocessing) to 74.93\% (s123, truncate preprocessing), a 7.68\pp{} spread that conflates preprocessing strategy, checkpoint selection method, and seed. The two strategies produce different effective training sets (67,343 vs.\ 70,748 samples) and different checkpoint selection regimes. The qualitative ranking \cls{} $>$ \cwm{} holds under both strategies (Table~\ref{tab:taxonomy}).
452	
453	\paragraph{\traj{} training regime.} \traj{} uses a different training configuration: smaller training set (${\sim}$400 repo-level variants vs.\ ${\sim}$70K per-test instances), higher learning rate ($2{\times}10^{-4}$ vs.\ $5{\times}10^{-5}$), and variant-level labels. This asymmetry is inherent to the formulation (trajectory-level labels are only available at variant granularity), but precludes training-data-controlled comparison at repo level. The downsample ablation confirms the \cls{} formulation advantage persists at matched data volume (80.74\% vs.\ 72.92\%; Appendix~\ref{app:downsample}), though it controls for training volume but not label granularity (per-test vs.\ variant-level). Crucially, \traj{} achieves statistical equivalence with \cls{} at function level (${\leq}$1.3\pp{}, \S\ref{sec:func_results}), demonstrating the formulation itself is viable; the repo-level gap is more consistent with data scarcity (${\sim}$400 variants vs.\ ${\sim}$70K per-test instances) than with a formulation-level limitation.
454	
455	\paragraph{\cwm{} scale and pretraining.} Our \cwm{} baseline uses 4--8B LoRA fine-tuning without execution trace pretraining. The original Code World Model~\cite{meta2025cwm} uses 32B parameters with mid-training on execution traces, a fundamentally different training regime. At larger scale or with execution-trace pretraining, the generation bottleneck observed here may diminish: larger models produce more coherent long-form outputs, and execution trace exposure may improve output format compliance. This is the primary limitation: all repo-level \cwm{} conclusions are conditional on the ${\leq}$8B LoRA regime.
456	
457	Despite these confounds, the repo-level \cls{}--\cwm{} gap (19--26\pp{}) exceeds any single assessed confound. Even under worst-case compounding (${\sim}$11.5\pp{}), the gap retains ${\geq}$7.5\pp{} margin; confounds predominantly disadvantage \cwm{}. However, correlated confounds and limited seed coverage mean definitive causal attribution requires multi-seed replication. At $n{=}48$, the minimum detectable effect (MDE) is ${\sim}$25\pp{}~\cite{hoenig2001}; the \cls{}--\cwm{} gap (29--35\pp{}) exceeds this threshold, while the \cls{}--\traj{} gap ($<$10\pp{}) falls below it, consistent with our TOST equivalence finding. Holm-Bonferroni correction across the four primary comparisons ($k{=}4$) confirms both the \cls{}--\cwm{} gap (adjusted $p{=}0.012$) and function-level equivalence (adjusted $p{=}0.021$) survive; the repo-level \cwm{}--\traj{} comparison is directionally consistent but does not survive correction (adjusted $p{=}0.078$; Table~\ref{tab:holm}). The consistent direction across both model families and all tested configurations supports a formulation-level explanation, though definitive causal attribution requires future experiments addressing each confound individually.
458	
459	
460	\section{Extended Limitations}
461	\label{app:limitations}
462	
463	The same-size 4B comparison uses a single seed; \cls{} 4B seed 123 (val-best ckpt-800) achieves only 75.33\% test accuracy (+2.4\pp{} above majority baseline); val-best selection at an early checkpoint (step 800) amplifies the val-test distribution shift observed across all configurations. The \cwm{} 8B comparison is also single-seed. The validation and test sets have zero problem overlap but differ in mutation type composition (Table~\ref{tab:mutation_distribution}): \texttt{operator\_swap} shifts from 19.1\% (val) to 34.3\% (test), the largest single-type distribution mismatch (+15.2\pp{}). All repo-level results use val-selected checkpoints, and checkpoint selection variance could contribute to observed differences. Our training data is synthetically constructed from mutation operators rather than real developer patches. While mutation testing literature establishes that mutants are reasonable proxies for real faults in test effectiveness studies~\cite{andrews2005mutation,just2014mutants}, these findings concern mutation \emph{adequacy} (whether tests that kill mutants also detect real faults), not whether verifiers trained on mutants transfer to real patches. However, the coupling effect underlying these results supports \emph{relative ranking} validity: a domain shift from synthetic mutations to real bugs may affect absolute accuracy levels, but our core finding---that formulation choice matters at repo level but not function level---concerns relative performance ordering, which is expected to be preserved under distributional shifts that affect all formulations equally. The synthetic-to-real transfer gap for absolute accuracy remains untested. The \traj{} training configuration differs from \cls{}/\cwm{}: smaller training set (${\sim}$400 vs.\ ${\sim}$70K instances), different learning rate ($2{\times}10^{-4}$ vs.\ $5{\times}10^{-5}$), and variant-level evaluation ($n{=}48$ vs.\ per-test $n{=}9{,}784$). The function-level TOST equivalence ($p = 0.007$, $\pm$2\pp{}) is computed on 523 matched variant-level instances across 5 seeds; 2 of 5 seeds use NF4 quantization. Restricting to three bfloat16 seeds yields a comparable mean gap ($-$0.45\pp{}) but wider confidence interval (df${=}$2); the TOST $p$-value increases from 0.007 to 0.128, which reflects reduced statistical power rather than a shift in the point estimate. The NF4 seeds contribute precision (narrowing the CI) without shifting the mean, consistent with precision being comparable across both quantization levels at function level. Repo-level \cls{}--\traj{} comparison is tentative due to configuration and granularity differences.
464	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "89ab2aac-b481-47ea-a6ab-83dcca8575c1",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "51b2f810-69dc-4719-83b4-50bb41264598",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex",
      "content": "\\appendix\n\n\\section{Oracle Accuracy-Utility Analysis}\n\\label{app:oracle}\n\nWe stratify SWE-bench Verified instances by F2P test count $T$, comparing per-test vs.\\ trajectory-level oracle resolve rates under i.i.d.\\ and block-correlated error models (ICC $= 0.191$, from function-level analysis; \\S\\ref{sec:equivalence}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Oracle accuracy-utility frontier: per-test advantage stratified by F2P test count ($T$) on SWE-bench Verified (500 instances). Block-correlated model uses function-level ICC $= 0.191$ (from function-level analysis, \\S\\ref{sec:equivalence}). P2P regression rate: 1.04\\% mean, 0\\% median.}\n\\label{tab:oracle}\n\\resizebox{\\columnwidth}{!}{%\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{$T$} & \\textbf{Inst.\\%} & \\textbf{i.i.d.\\ (\\pp{})} & \\textbf{Block (\\pp{})} & \\textbf{Contrib.\\%} \\\\\n\\midrule\n$1$ & 68.7 & $-$0.04 & $-$0.09 & $\\approx$0 \\\\\n$2$ & 19.1 & 18.49 & 31.69 & 55.3 \\\\\n$3$--$5$ & 7.1 & 25.00 & 40.74 & $\\approx$26 \\\\\n$\\geq 6$ & 5.1 & 30.00 & 40.06 & $\\approx$19 \\\\\n\\midrule\n\\textbf{All} & 100.0 & --- & \\textbf{10.93} & 100.0 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_oracle_stratified.pdf}\n\\caption{Oracle per-test advantage by F2P test count $T$. Advantage is zero at $T{=}1$ (68.7\\%) and concentrates at $T{=}2$ (19.1\\%, contributing 55.3\\% of total advantage).}\n\\label{fig:oracle_stratified}\n\\end{figure}\n\nTable~\\ref{tab:oracle} and Figure~\\ref{fig:oracle_stratified} reveal a sharp concentration: at $T = 1$ (68.7\\% of instances), per-test and trajectory-level are informationally equivalent. The advantage materializes at $T = 2$ (19.1\\%), where block-correlated advantage reaches 31.69\\pp{} (55.3\\% of total). The overall block-correlated advantage is 10.93\\pp{}, driven by the $T \\geq 2$ minority. Block correlation amplifies relative to i.i.d.: at $T = 2$, 31.69\\pp{} vs.\\ 18.49\\pp{} (1.7$\\times$). P2P regression is negligible (1.04\\% mean, 0\\% median); the practical value concentrates in F2P discrimination.\n\n\\paragraph{Sensitivity to ICC estimate.}\nThe analysis above uses ICC $= 0.191$ from function-level analysis (\\S\\ref{sec:equivalence}), where mean cluster size $\\bar{k} \\approx 16.5$ yields DEFF $= 3.97$. At repository level, within-problem correlation is substantially stronger: ICC $= 0.3146$ with DEFF $= 114.4$ (\\S\\ref{sec:repo}), a consequence of the larger and more heterogeneous test suites in SWE-bench Verified problems. Under higher ICC, within-problem errors cluster more tightly and amplify the block-correlated per-test advantage at each $T$ stratum; the correction from i.i.d.\\ to block-correlated grows monotonically with ICC. The function-level ICC $= 0.191$ used in Table~\\ref{tab:oracle} thus provides a conservative lower bound on the per-test advantage. The repo-level correlation structure would yield an even larger gap between per-test and trajectory-level oracle resolve rates, which strengthens the case for per-test granularity at repository-level complexity.\n\n\\section{Ablation Studies}\n\\label{app:ablations}\n\n\\paragraph{LoRA rank sensitivity.}\nAll \\cwm{} experiments use LoRA rank $r{=}16$. To test whether this capacity constraint handicaps \\cwm{}, we train rank-32 variants (seed 42), doubling adapter parameters.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{LoRA rank ablation for \\cwm{} 4B (seed 42, 3 epochs, lr $= 2{\\times}10^{-4}$). Rank-16 seed variance: 0.53\\pp{} (seeds 42 vs.\\ 456).}\n\\label{tab:rank_ablation}\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Config} & \\textbf{$\\alpha/r$} & \\textbf{Acc (\\%)} & \\textbf{Fail \\fone{}} & \\textbf{Pass \\fone{}} & \\textbf{$\\Delta$} \\\\\n\\midrule\n$r{=}16$, $\\alpha{=}32$ & 2 & \\textbf{87.51} & --- & --- & --- \\\\\n$r{=}32$, $\\alpha{=}32$ & 1 & 87.00 & 87.1 & 86.9 & $-$0.51 \\\\\n$r{=}32$, $\\alpha{=}64$ & 2 & 87.04 & 87.27 & 86.79 & $-$0.47 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nBoth rank-32 variants fall within the 2-seed variance of the rank-16 baseline (0.53\\pp{} between seeds 42 and 456). The $\\alpha{=}64$ variant (matching the baseline $\\alpha/r{=}2$ ratio) rules out the confound that the $\\alpha{=}32$ result might reflect reduced effective scaling rather than rank insensitivity. This is consistent with \\cwm{}'s function-level performance being bounded by output-format constraints rather than adapter capacity.\n\n\\paragraph{Majority voting.}\nMajority voting ($K{=}3$) decreases accuracy from 87.51\\% to 86.83\\% ($-$0.68\\pp{}): errors are systematic rather than stochastic, so sampling-based ensembles do not help.\\footnote{These majority-voting values were computed from an unverified checkpoint and may differ slightly from the val-best checkpoint results.}\n\n\\paragraph{Sequence-length ablation details.}\nBoth formulations are trained with \\texttt{max\\_seq\\_length}$=$2,048. At inference, \\cwm{} reserves \\texttt{max\\_new\\_tokens}$=$512, leaving ${\\sim}$1,536 effective input tokens; \\cls{} allocates nearly all context to input (5,120--8,192 tokens). A matched-context ablation (\\cls{} 8B at 2,048 tokens) achieves 83.04\\%, only 1.44\\pp{} below the 8,192-token evaluation (84.48\\%), though truncation introduces 136 unparseable outputs (1.39\\% of test samples). The matched-context gap (\\cls{}@2,048 vs.\\ \\cwm{}@2,048) is 25.00\\pp{} (98\\% of the full 25.59\\pp{} gap), confirming that input context disparity explains at most 3\\% of the difference.\n\n\\paragraph{Training data size control.}\n\\label{app:downsample}\nTo control for the training set size asymmetry between \\cls{} (${\\sim}$70K instances) and \\traj{} (386 variant-level instances, ${\\sim}$8K per-test equivalents, at repo level), we downsample \\cls{} training data to match \\traj{} in data volume. Downsampled \\cls{} (Qwen3-4B, seed 42) achieves 80.74\\% repo-level per-test accuracy, only 2.89\\pp{} below the full-data \\cls{} (83.63\\%) and still 7.82\\pp{} above \\traj{} (72.92\\%). The \\cls{} formulation advantage is not attributable to training data volume.\n\n\\paragraph{Few-shot prompting baselines.}\n\\label{app:few_shot}\nWe evaluate 3-shot in-context learning at repo level to test whether prompting strategy closes the gap to fine-tuned models. Table~\\ref{tab:few_shot} reports both per-test and variant-level accuracy.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Repo-level prompting baselines (per-test $n{=}9{,}784$; variant-level $n{=}48$). Majority baseline: 72.96\\% per-test, 54.17\\% variant-level.}\n\\label{tab:few_shot}\n\\setlength{\\tabcolsep}{4pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & \\textbf{0-shot (per-test)} & \\textbf{3-shot (per-test)} & \\textbf{3-shot (variant)} \\\\\n\\midrule\nQwen3-8B & 49.90\\% & 71.61\\% & 45.83\\%\\textsuperscript{$\\ast$} \\\\\nDeepSeek-6.7B & 48.54\\% & 46.28\\% & 45.83\\%\\textsuperscript{$\\ast$} \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{2pt}\n{\\footnotesize \\textsuperscript{$\\ast$}Both models achieve 45.83\\% by correctly classifying all 22 unresolved variants and zero resolved variants (22/48 = 45.83\\%), equivalent to an always-predict-unresolved baseline. The 100\\% overlap in variant-level predictions confirms complete degradation at task-relevant granularity.}\n\\end{table}\n\nBoth models converge to exactly 45.83\\% variant-level accuracy under 3-shot prompting, below majority baseline (54.17\\%). Variant-level analysis reveals this is not a coincidence: both models correctly classify all 22 unresolved variants and zero resolved variants, equivalent to an always-predict-unresolved baseline with 100\\% prediction overlap. Per-test accuracy diverges sharply (Qwen3-8B 71.61\\% vs.\\ DeepSeek 46.28\\%), but this divergence is entirely superficial: Qwen3-8B predicts pass on nearly all tests, inflating per-test accuracy on a pass-heavy dataset (72.96\\% pass rate) without genuine discriminative ability. Per-test metrics can thus severely misrepresent baseline capability; variant-level evaluation is necessary to detect complete degradation. Neither 0-shot nor few-shot prompting approaches fine-tuned performance (82--84\\% per-test); fine-tuning is a necessary condition for repo-level verification.\n\n\\section{Repo-Level Per-Mutation Breakdown}\n\\label{app:repo_mutation}\n\nTable~\\ref{tab:mutation_breakdown} compares per-mutation accuracy at repo level. \\cls{} produces 0\\% unparseable outputs; all values are direct classification accuracy. \\cwm{} overall accuracy includes default-pass assignment for unparseable outputs (see \\S\\ref{sec:repo}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-mutation test accuracy (\\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \\cls{} 8B reports two seeds; $\\Delta$ is mean 4B$\\to$8B gain for \\cls{}. \\cwm{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\\%, parseable acc 23.5\\%).}\n\\label{tab:mutation_breakdown}\n\\resizebox{\\columnwidth}{!}{%\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{lccccccc}\n\\toprule\n\\textbf{Mutation} & \\textbf{$n$} & \\textbf{CLS 4B} & \\textbf{CLS 8B s42} & \\textbf{CLS 8B s123} & \\textbf{CWM 4B} & \\textbf{CWM 8B} & \\textbf{$\\Delta$ CLS} \\\\\n\\midrule\ngold & 4,633 & 98.25 & 96.24 & 99.60 & 66.72 & 80.06 & $-$0.33 \\\\\noperator\\_swap & 3,357 & 78.91 & 81.38 & 82.60 & --- & 54.57 & +3.08 \\\\\noff\\_by\\_one & 183 & 58.47 & 86.89 & 79.20 & --- & 63.39 & \\textbf{+24.58} \\\\\nreturn\\_value & 562 & 67.97 & 75.44 & 66.40 & --- & 49.11 & +2.95 \\\\\nboundary\\_removal & 1,049 & 46.90 & 46.90 & 44.90 & --- & 42.23 & $-$1.00 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nTable~\\ref{tab:cwm_mutation_parse} shows that \\cwm{} generation quality degrades from 4B to 8B across all mutation types.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{\\cwm{} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\\%) for gold at both scales.}\n\\label{tab:cwm_mutation_parse}\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{Parse Rate (\\%)}} & \\multicolumn{2}{c}{\\textbf{Parse Acc (\\%)}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\n\\textbf{Mutation} & \\textbf{4B} & \\textbf{8B} & \\textbf{4B} & \\textbf{8B} \\\\\n\\midrule\ngold & 43.5 & 23.9 & 23.5 & 16.5 \\\\\noperator\\_swap & 56.9 & 21.2 & 63.1 & 58.8 \\\\\noff\\_by\\_one & 4.4 & 27.3 & 0.0 & 38.0 \\\\\nreturn\\_value & 48.8 & 26.9 & 27.0 & 56.9 \\\\\nboundary\\_removal & 30.6 & 51.8 & 59.2 & 51.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nKey findings: (1)~Gold parse rate collapses from 43.5\\% to 23.9\\% at 8B; the simplest generation target (unmodified code, where all tests pass) degrades most, consistent with a fundamental generation bottleneck rather than task difficulty. (2)~Among parseable outputs, gold accuracy is 16.5--23.5\\%: the model generates outputs that fail exact-match even for correct code. (3)~\\texttt{off\\_by\\_one} is an anomaly: parse rate \\emph{increases} from 4.4\\% to 27.3\\%, but this is from an extremely low base ($n{=}8$ parseable at 4B), making both directions unreliable for this category.\n\n\\section{Variant-Level Accuracy}\n\\label{app:variant_level}\n\nTable~\\ref{tab:variant_level} reports variant-level accuracy ($n{=}48$) alongside per-test accuracy for all repo-level configurations. For \\cls{}, the aggregation penalty (per-test $\\to$ variant-level drop) ranges from 1\\pp{} to 19\\pp{} and is largest for models with low fail recall under the all-pass rule. \\cwm{} variant-level accuracy (48--52\\%) falls at or below the majority baseline, consistent with format collapse as the dominant failure mode.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Repo-level per-test vs.\\ variant-level accuracy ($n{=}48$ variants). Penalty = per-test $-$ variant-level. \\traj{} predicts variant outcomes directly (no aggregation). Variant-level majority baseline: 54.17\\% (26/48).}\n\\label{tab:variant_level}\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Seed} & \\textbf{Per-test (\\%)} & \\textbf{Variant (\\%)} & \\textbf{Penalty (\\pp{})} & \\textbf{Fail Recall (\\%)} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{\\cls{}}} \\\\\nQwen3-8B & s42 & 84.48 & 72.92 & 11.56 & 56.76 \\\\\nQwen3-8B & s123 & 85.60 & 81.25 & 4.35 & 51.44 \\\\\nQwen3-4B & s42 & 83.63 & 64.58 & 19.05 & 48.72 \\\\\nDeepSeek-6.7B & s42 (e1) & 82.61 & 81.25 & 1.36 & 51.02 \\\\\nDeepSeek-6.7B & s42 (e3) & 82.51 & 79.17 & 3.34 & 38.47 \\\\\nDeepSeek-6.7B & s123 & 74.93 & 56.25 & 18.68 & ${\\sim}$13.72 \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{\\cwm{}}} \\\\\nQwen3-8B & s42 & 65.17 & 52.08 & 13.09 & --- \\\\\nDeepSeek-6.7B$^\\dagger$ & s123 & --- & 47.92 & --- & --- \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{\\traj{}}} \\\\\nQwen3-4B & s42 & --- & 72.92 & --- & --- \\\\\nQwen3-8B & s42 & --- & 70.83 & --- & --- \\\\\nDeepSeek-6.7B & 3-seed & --- & 77.08 $\\pm$ 3.61 & --- & --- \\\\\n\\midrule\nMajority & --- & 72.96 & 54.17 & --- & --- \\\\\n\\bottomrule\n\\end{tabular}}\n\\vspace{2pt}\n\n{\\footnotesize $^\\dagger$Evaluated on ${\\sim}$75\\% of test instances (7210--7668 of 9784). DeepSeek \\traj{} Table~\\ref{tab:repo_level} reports 3 seeds (42/123/456) for alignment with \\cls{}/\\cwm{} seed coverage; three supplementary seeds (0/789/999) yield 75.0\\%, 66.7\\%, 79.2\\% respectively (6-seed mean 75.35 $\\pm$ 5.00\\%), consistent in direction.}\n\\end{table}\n\n\\section{Training Hyperparameters}\n\\label{app:hyperparams}\n\nTable~\\ref{tab:hyperparams} lists all hyperparameters used for fine-tuning. Both \\cls{} and \\cwm{} share the same LoRA configuration, optimizer, and training schedule; the only differences are per-device batch size, gradient accumulation steps (adjusted to maintain identical effective batch size of 32 across model sizes), and learning rate (DeepSeek-Coder uses $2{\\times}10^{-4}$ vs.\\ $5{\\times}10^{-5}$ for Qwen3, selected via grid search over $\\{5{\\times}10^{-5}, 1{\\times}10^{-4}, 2{\\times}10^{-4}\\}$ on held-out validation loss).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Training hyperparameters for \\cls{}/\\cwm{} configurations. \\traj{} models use lr $= 2{\\times}10^{-4}$ due to the smaller training set (${\\sim}$8K function-level instances vs.\\ ${\\sim}$70K for \\cls{}/\\cwm{}); other hyperparameters are shared.}\n\\label{tab:hyperparams}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{ll}\n\\toprule\n\\multicolumn{2}{l}{\\textbf{Shared across all configurations}} \\\\\n\\midrule\nLoRA rank / alpha / dropout & 16 / 32 / 0.05 \\\\\nLoRA targets & \\texttt{q/k/v/o\\_proj} \\\\\nOptimizer & AdamW ($\\beta_1{=}0.9$, $\\beta_2{=}0.999$) \\\\\nLR scheduler & Linear \\\\\nEffective batch size & 32 \\\\\nMax sequence length & 2,048 \\\\\nEpochs & 3 \\\\\nPrecision & bf16 \\\\\nGradient checkpointing & \\checkmark \\\\\nSeeds (function) & \\{42, 123, 456, 789, 0\\}\\textsuperscript{$b$} \\\\\nSeeds (repo) & \\{42, 123, 456\\}\\textsuperscript{$c$} \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{6pt}\n\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\multicolumn{4}{l}{\\textbf{Model-family--specific parameters}} \\\\\n\\midrule\n& \\textbf{Qwen3-4B} & \\textbf{Qwen3-8B} & \\textbf{DS-6.7B} \\\\\n\\midrule\nLearning rate & 5e-5 & 5e-5 & 2e-4 \\\\\nWeight decay & 0.01 & 0.01 & 0.0 \\\\\nWarmup ratio & 0.05 & 0.05 & 0.1 \\\\\nBatch / grad.\\ accum.\\ (\\cls{}) & 2 / 16 & 1 / 32 & 2 / 16 \\\\\nBatch / grad.\\ accum.\\ (\\cwm{}) & 1 / 32 & 1 / 32 & 1 / 32 \\\\\nTraining samples & 70,748 & 70,748 & 67,343--70,748\\textsuperscript{$a$} \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{2pt}\n{\\footnotesize $^a$DeepSeek \\cls{} canonical run (s42) uses drop preprocessing, which excludes 3,405 sequences exceeding max length (67,343 of 70,748). The s123 run uses truncate preprocessing (70,748 samples) but produces NaN validation loss. See \\S\\ref{sec:setup}. $^b$Seeds 789 and 0 use NF4 quantization; others use bf16. $^c$Repo-level seed coverage varies by configuration; see Table~\\ref{tab:repo_level} caption for per-model counts.}\n\\end{table}\n\n\\paragraph{Data processing.} DeepSeek CWM seeds use \\texttt{train\\_unified.py}, which drops samples exceeding \\texttt{max\\_seq\\_length} (3{,}405 of 70{,}748 samples, 4.8\\%). Qwen CWM seeds use \\texttt{train\\_repo\\_cwm.py}, which truncates and retains all samples. This difference affects total training steps (${\\sim}$12{,}627 vs.\\ ${\\sim}$13{,}266 for DeepSeek, ${\\sim}$6{,}633 for Qwen) but not the training data distribution, as dropped samples are uniformly distributed across labels.\n\n\\paragraph{Prompt templates.} Prompt templates for all formulations (\\cls{}, \\cwm{}, \\traj{}) are provided in the code repository. \\cls{} uses a binary classification template (``Does this test pass or fail?''); \\cwm{} uses an execution simulation template (``What is the output of this test?''); \\traj{} uses a variant-level verdict template (``Is this patch resolved or unresolved?'').\n\n\\paragraph{Mutation operators.} We use five mutation types: (1)~\\emph{gold}: unmodified code (all tests pass); (2)~\\emph{operator\\_swap}: replaces comparison or arithmetic operators (e.g., \\texttt{<} $\\to$ \\texttt{<=}); (3)~\\emph{off\\_by\\_one}: shifts loop bounds or array indices by $\\pm$1; (4)~\\emph{return\\_value}: modifies return statements (e.g., negating a boolean, changing a constant); (5)~\\emph{boundary\\_removal}: removes conditional guards or boundary checks. Mutation operators were applied using AST-level transformation; variants that did not alter any test outcome were discarded.\n\n\\paragraph{Compute budget.}\nAll experiments were conducted on NVIDIA RTX 5090 GPUs. Training time is approximately 1.5 hours per run for 4B models and 2 hours for 8B models. Total compute budget: ${\\sim}$370 GPU-hours across 223 completed runs (135 successful, 88 failed/killed; ${\\sim}$46 unique configurations including seeds, formulations, model sizes, and ablations).\n\n\\section{Val-Test Mutation Type Distribution}\n\\label{app:mutation_distribution}\n\nTable~\\ref{tab:mutation_distribution} reports the mutation type composition of the repo-level validation and test sets. The most notable shift is \\texttt{operator\\_swap}, which nearly doubles from val (19.1\\%) to test (34.3\\%), while \\texttt{off\\_by\\_one} shrinks from 10.0\\% to 1.9\\%.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Repo-level mutation type distribution: validation vs.\\ test set, with per-type \\cls{} accuracy at two model sizes (seed 42). Shift = test\\% $-$ val\\%.}\n\\label{tab:mutation_distribution}\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Mutation Type} & \\textbf{Val (\\%)} & \\textbf{Test (\\%)} & \\textbf{Shift} & \\textbf{\\cls{} 4B} & \\textbf{\\cls{} 8B} \\\\\n\\midrule\ngold & 45.2 & 47.4 & +2.2 & 98.3 & 96.2 \\\\\noperator\\_swap & 19.1 & 34.3 & +15.2 & 78.9 & 81.4 \\\\\nboundary\\_removal & 15.0 & 10.7 & $-$4.3 & 46.9 & 46.9 \\\\\nreturn\\_value & 10.7 & 5.7 & $-$5.0 & 68.0 & 75.4 \\\\\noff\\_by\\_one & 10.0 & 1.9 & $-$8.1 & 58.5 & 86.9 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThe \\texttt{operator\\_swap} shift is the primary source of val-test distribution mismatch. Since \\cls{} achieves moderate accuracy on this type (78.9--81.4\\%), the over-representation in the test set does not systematically bias overall accuracy estimates in either direction. Two boundary observations are notable: (1)~\\texttt{boundary\\_removal} represents a scale-invariant difficulty ceiling at ${\\sim}$47\\% across both model sizes: this mutation type resists capacity scaling; (2)~\\texttt{off\\_by\\_one} shows the largest scaling gain (+28.4\\pp{}, 58.5\\%$\\to$86.9\\%) but its small test share (1.9\\%) limits its contribution to overall accuracy differences across scales.\n\n\\section{Qualitative Error Analysis}\n\\label{app:qualitative}\n\nTo complement the quantitative divergence reported in \\S\\ref{sec:repo}, we examine representative errors from each formulation at repository level.\n\n\\paragraph{\\cwm{} failure modes.}\nTwo patterns account for the majority of unparseable \\cwm{} outputs on Qwen3. (1)~\\emph{Task misunderstanding}: the model generates a complete simulated test runner log (test names, timing, summary lines) rather than a pass/fail verdict. For instance, on \\texttt{django\\_\\_django-14315}, the model outputs a fabricated 1,248-token Django test execution trace with hallucinated test names that do not exist in the target file. The model confuses ``predict test outcome'' with ``simulate test execution environment.'' (2)~\\emph{Autoregressive degeneration}: the model enters a repetitive loop (e.g., repeating \\texttt{from \\_pytest.config import \\_parse\\_pytest\\_args} until truncation at 4,542 tokens). Both patterns produce zero usable signal and default to the majority-class label. This explains why unparseable predictions carry higher accuracy than parseable ones (\\S\\ref{sec:repo}).\n\n\\paragraph{\\cls{} failure modes.}\n\\cls{} errors concentrate in two categories requiring multi-step reasoning. False positives arise from \\emph{cross-concern value propagation}: a boundary removal mutation in \\texttt{pytest} converts a guarded attribute access (\\texttt{if xfailed and not xfailed.run}) to \\texttt{if True:}, causing a NoneType error on tests exercising unrelated skip marks. The model fails to trace the None path through the pytest hook lifecycle. False negatives arise from \\emph{mathematical equivalence}: on \\texttt{HumanEval/130} (Tribonacci variant), the model predicts failure for correct code because verifying the self-referential recurrence requires algebraic substitution rather than syntactic inspection. This single problem accounts for 17\\% of all function-level false negatives.\n\n\\paragraph{Complementarity.}\nThese failure patterns operate at different levels: \\cwm{} fails at the format level (producing no usable signal), while \\cls{} fails at the reasoning level (producing a confident but incorrect binary verdict). Both formulations are FP-dominant (over-predict failure), but \\cwm{}'s higher FP rate (70.3\\% vs.\\ 56.5\\%) means it over-predicts failure on instances \\cls{} correctly classifies, producing partial complementarity (oracle combination: 90.63\\%; \\S\\ref{app:extended_analysis}, paragraph a).\n\n\\section{Extended Analysis}\n\\label{app:extended_analysis}\n\n\\paragraph{(a) Error complementarity.}\n\\cls{} and \\cwm{} are both FP-dominant at function level but at different rates, producing partial complementarity. Among \\cls{} errors (seed 42), 56.5\\% are false positives (PASS $\\to$ FAIL); among \\cwm{} errors, 70.3\\% are false positives. Both formulations over-predict failure, but \\cwm{}'s stronger FP bias means it incorrectly rejects passing tests that \\cls{} correctly accepts. An oracle combination achieves 90.63\\% accuracy (1713/1890 correct, 177 both-wrong; +2.80\\pp{} over the best single formulation, \\cls{} 87.83\\%; single-seed estimate, seed 42). The complementarity arises from different \\emph{degrees} of fail-bias rather than opposite error directions: \\cwm{}'s generation bottleneck produces aggressive failure predictions, while \\cls{}'s single-token output is more calibrated. Ensemble approaches exploiting this degree difference are a natural direction.\n\n\\paragraph{(b) CWM error mode breakdown.}\nAmong unparseable \\cwm{} outputs (Qwen3, repo-level), 76.9\\% contain no execution keywords; 22.9\\% contain ambiguous co-occurring pass/fail keywords. Format compliance varies sharply across repositories (scikit-learn: near-zero unparseable; sphinx: 100\\%); repository-specific code patterns interact with the model's generation capabilities in complex ways. This per-repository variation is consistent with a model/tokenizer-specific failure rather than a formulation-level one.\n\n\\paragraph{(c) Relaxed matching does not rescue \\cwm{}.}\nRelaxed matching (tolerating format deviations, L0--L4) \\emph{decreases} \\cwm{} accuracy: 58.04\\%$\\to$56.98\\% (seed 42) and 59.09\\%$\\to$55.91\\% (seed 123). Unparseable predictions default to the majority class (pass, 72.96\\%), which outperforms the model's own parseable predictions (42--53\\%). The divergence widens from 26\\pp{} to 28\\pp{} under relaxed matching. This rules out the hypothesis that parsing strictness inflates the observed gap. Constrained decoding~\\cite{willard2023outlines} could enforce format compliance but would not address the semantic accuracy deficit among parseable outputs.\n\n\\paragraph{(d) Variance compression.}\n\\cwm{}'s 5-seed standard deviation (0.37\\pp{}) is lower than \\cls{} (0.78\\pp{}) and \\traj{} (0.97\\pp{}) at function level. If \\cwm{} performance is capped by output-format constraints at a given complexity level, seed-to-seed variability is compressed relative to formulations whose performance depends more on learned representations.\n\n\\paragraph{(e) Per-test precision and recall.}\n\\cls{} achieves fail \\fone{} 87.59\\% (precision 86.20\\%, recall 89.04\\%) at seed 42.% derived from overlap analysis (error_overlap_matched_seed.json); FP=130, FN=100, TP=848, TN=812\nMulti-F2P instances (6--10 tests) reach 96.3\\% accuracy, consistent with the oracle finding that per-test granularity is most valuable for complex instances.\n\n\\paragraph{(f) Block correlation.}\nWithin-problem errors are correlated (ICC $= 0.191$, DEFF $= 3.97$, 2.81$\\times$ more all-correct problems than i.i.d.\\ expectation). All statistical tests use clustered bootstrap accordingly.\n\n\\paragraph{(g) Failed interventions.}\nWe systematically tested four interventions targeting different hypothesized causes of \\cwm{} repo-level degradation; all failed:\n\n\\begin{itemize}[leftmargin=*,itemsep=1pt,topsep=2pt]\n\\item \\textbf{Capacity (rank 32):} Doubling adapter parameters does not improve accuracy ($-$0.51\\pp{}, within seed variance; Appendix~\\ref{app:ablations}).\n\\item \\textbf{Majority voting ($K{=}3$):} Accuracy \\emph{decreases} by 0.68\\pp{} (87.51\\%$\\to$86.83\\%); 93.3\\% of samples are unanimous across passes, and net flips are negative ($-$13), indicating errors are systematic bias rather than stochastic noise.\n\\item \\textbf{Relaxed matching (L0--L4):} Tolerating format deviations \\emph{decreases} accuracy from 58.04\\% to 56.98\\% (seed 42; Appendix~\\ref{app:extended_analysis}(c)), because unparseable predictions default to the majority class (pass, 72.96\\%), which outperforms the model's own parseable predictions (38--43\\%).\n\\item \\textbf{Model scaling (4B$\\to$8B):} Parseable-only accuracy decreases (42.88\\%$\\to$38.52\\%) while unparseable rate increases (53.7\\%$\\to$73.8\\%); the apparent accuracy gain is entirely a default-assignment artifact (\\S\\ref{sec:repo}).\n\\end{itemize}\n\n\\noindent Each intervention targets a distinct alternative explanation (insufficient capacity, random noise, parsing strictness, model scale); the uniform failure across all four confirms the bottleneck is formulation-level---output space complexity at repo level exceeds what ${\\leq}$8B generation models can handle, independent of these surface-level factors.\n\n\\paragraph{(h) Per-mutation scaling patterns.}\nScaling benefits are highly non-uniform across mutation types (Table~\\ref{tab:mutation_breakdown}). \\texttt{off\\_by\\_one} shows the largest \\cls{} scaling gain: 58.5\\% (4B) to 86.9\\% (8B, $+$28.4\\pp{}). In contrast, \\texttt{boundary\\_removal} is scale-invariant at ${\\sim}$47\\% across both sizes, which marks an intrinsic difficulty ceiling. For \\cwm{}, gold mutation parse rate collapses from 43.5\\% (4B) to 23.9\\% (8B) despite being the simplest target: generation capability degrades even for trivially correct code at larger scale within Qwen3. The val-test mutation type distribution differs notably (\\texttt{operator\\_swap} shifts from 19.1\\% to 34.3\\%; Table~\\ref{tab:mutation_distribution}), but this shift does not systematically bias overall accuracy because \\cls{} performance on \\texttt{operator\\_swap} (78.9--81.4\\%) is close to the overall mean.\n\n\\paragraph{(i) Inference efficiency.}\n\\cls{} achieves 217$\\times$ higher throughput than \\cwm{} at repo level (853 vs.\\ 3.9 inferences/min; Qwen3-4B, RTX 5090, 100 samples, avg ${\\sim}$1,040 input tokens). The speedup derives directly from the formulation: classification requires a single output token, whereas \\cwm{} generates an average of 477 tokens per inference. Median latency is 48ms (\\cls{}) vs.\\ 16.3s (\\cwm{}). At the observed unparseable rate of 73.8\\% (8B), the majority of \\cwm{}'s generation budget produces tokens that cannot yield a valid verdict. This \\cls{}--\\cwm{} efficiency gap is an inherent property of the formulation difference (1 vs.\\ $O(L)$ output tokens) and should generalize across models, unlike the accuracy divergence which may be model-contingent.\n\nThe \\cls{}--\\traj{} efficiency comparison is more nuanced, because \\cls{} makes one call per test while \\traj{} makes one call per instance. Per-call, \\cls{} is 20--138$\\times$ faster (depending on input length: 47ms for short contexts vs.\\ 2,632ms for \\traj{}). However, the per-instance effective speedup depends on test count $|T|$: at function level ($|T| \\approx 2.3$), \\cls{} is ${\\sim}$24$\\times$ faster (108ms vs.\\ 2,632ms per instance); at repo level ($|T| \\approx 12.3$, ${\\sim}$70ms/call with longer inputs), \\cls{} is ${\\sim}$3$\\times$ faster (861ms vs.\\ 2,631ms). A crossover exists at $|T| \\approx 50$ tests, beyond which \\traj{}'s single-call amortization dominates. This boundary condition is informative for deployment: \\cls{} is strongly preferred for function-level and moderate repo-level test suites, while extremely large test suites ($>$50 tests per instance) favor trajectory-level efficiency despite its coarser diagnostic signal.\n\n\\paragraph{(j) Re-repair pilot.}\nWe tested whether per-test diagnostic feedback improves downstream repair. A Qwen3-8B repair agent received either per-test diagnostic signals (which specific tests failed and why) or binary accept/reject feedback, evaluated on 44 SWE-bench Verified instances. The diagnostic condition achieved accuracy no higher than the binary baseline ($A_1 = 52.3\\%$, $p = 0.42$, effect size $\\approx 0$). Per-test diagnostic information does not automatically translate to repair improvements at this scale. The negative result may reflect insufficient agent capability to exploit fine-grained feedback, insufficient sample size (at $n = 44$, statistical power is ${\\sim}$0.3 for a medium effect size), or a genuine limitation of the diagnostic-to-repair translation.\n\n\\section{TOST Margin Sensitivity}\n\\label{app:tost_sensitivity}\n\nTable~\\ref{tab:tost_sensitivity} reports the TOST equivalence $p$-value as a function of the equivalence margin, computed on the 5-seed variant-level \\cls{}--\\traj{} comparison (gap $= -$0.45\\pp{}, 523 variants, 114 clusters, clustered bootstrap).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{TOST margin sensitivity for \\cls{}--\\traj{} variant-level equivalence (5 seeds, 523 variants, 114 clusters). The smallest margin achieving equivalence at $\\alpha = 0.05$ is $\\pm$1.52\\pp{}.}\n\\label{tab:tost_sensitivity}\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{ccc}\n\\toprule\n\\textbf{Margin ($\\pm$\\pp{})} & \\textbf{$p$-value} & \\textbf{Equivalent ($\\alpha{=}0.05$)?} \\\\\n\\midrule\n1.0 & $\\gg$0.05 & No \\\\\n1.5 & 0.054 & No (borderline) \\\\\n\\textbf{1.52} & ${\\sim}$\\textbf{0.05} & \\textbf{Smallest margin} \\\\\n1.71 & 0.027 & Yes \\\\\n2.0 & 0.007 & Yes \\\\\n3.0 & $4.6{\\times}10^{-5}$ & Yes \\\\\n5.0 & $\\ll$0.001 & Yes \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe minimum equivalence margin is $\\pm$1.52\\pp{}, 0.48\\pp{} below our pre-specified $\\pm$2\\pp{} threshold. The $\\pm$2\\pp{} threshold was set based on deployment relevance rather than observed data: at function-level accuracy (85--88\\%), a 2\\pp{} per-test difference corresponds to ${\\sim}$38 additional errors across 1,890 tests (${\\sim}$2--3 problems out of 114), comparable in magnitude to between-seed standard deviation (0.37--0.97\\pp{}) and checkpoint selection noise ($<$1\\pp{}). Differences within this range do not reliably distinguish formulations from training noise in pipeline selection decisions.\n\n\n\\section{Variant-Level Effect Sizes}\n\\label{app:power}\n\nTable~\\ref{tab:variant_power} reports variant-level bootstrap confidence intervals for the repo-level formulation comparisons ($n{=}48$ variants). Following Hoenig and Heisey~\\cite{hoenig2001}, we report minimum detectable effect (MDE) rather than post-hoc observed power.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Variant-level bootstrap analysis ($n{=}48$). \\cls{}--\\cwm{} uses paired bootstrap (same variants, same seed); \\cls{}--\\traj{} uses unpaired bootstrap (per-variant \\traj{} predictions not archived for pairing). MDE at $n{=}48$: ${\\sim}$25\\pp{}.}\n\\label{tab:variant_power}\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Comparison} & \\textbf{Config} & \\textbf{$\\Delta$ (\\pp{})} & \\textbf{95\\% CI} & \\textbf{$p$} \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{\\cls{} vs.\\ \\cwm{} (paired)}} \\\\\n& Qwen3-8B & +29.17 & [10.42, 47.92] & 0.003 \\\\\n& DeepSeek-6.7B & +35.42 & [18.75, 50.05] & ${<}$0.001 \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{\\cls{} vs.\\ \\traj{} (unpaired)}} \\\\\n& Qwen3-4B & $-$4.17 & wide & 0.740 \\\\\n& Qwen3-8B & +8.33 & wide & 0.385 \\\\\n& DeepSeek-6.7B & 0.00 & wide & 1.000 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nAt $n{=}48$, the MDE is ${\\sim}$25\\pp{}. The \\cls{}--\\cwm{} gap (29--35\\pp{}) exceeds this threshold, confirming that $n{=}48$ is sufficient to detect the observed divergence. The \\cls{}--\\traj{} gaps ($<$10\\pp{}) fall well below the MDE: any true difference is too small to detect at this sample size, consistent with the function-level TOST equivalence (\\S\\ref{sec:equivalence}).\n\nThe \\cls{}--\\traj{} unpaired bootstrap produces wider confidence intervals than paired analysis would; \\traj{} per-variant predictions were not archived in a format that permits pairing. The \\cls{}--\\cwm{} paired comparison uses \\cls{} s123 vs.\\ \\cwm{} s42 (different seeds), but the CI lower bound of 10.42\\pp{} far exceeds the seed noise observed in function-level experiments ($<$2\\pp{}).\n\n\n\\section{Multiple Comparison Correction}\n\\label{app:holm}\n\nTable~\\ref{tab:holm} applies Holm-Bonferroni correction~\\cite{holm1979} to the four primary statistical comparisons across this study ($k{=}4$, family-wise $\\alpha{=}0.05$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Holm-Bonferroni correction for primary comparisons ($k{=}4$). Comparisons ranked by raw $p$-value; each tested against $\\alpha / (k - \\text{rank} + 1)$.}\n\\label{tab:holm}\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{clcccc}\n\\toprule\n\\textbf{Rank} & \\textbf{Comparison} & \\textbf{Raw $p$} & \\textbf{Factor} & \\textbf{Adj $p$} & \\textbf{Sig.?} \\\\\n\\midrule\n1 & Repo: \\cls{} vs \\cwm{} & 0.003 & $\\times$4 & 0.012 & \\checkmark \\\\\n2 & Func: \\cls{} vs \\traj{} (TOST $\\pm$2\\pp{}) & 0.0071 & $\\times$3 & 0.021 & \\checkmark \\\\\n3 & Repo: \\cwm{} vs \\traj{} & 0.039 & $\\times$2 & 0.078 & --- \\\\\n4 & Repo: \\cls{} vs \\traj{} & 0.385 & $\\times$1 & 0.385 & --- \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThe two core claims survive correction: the repo-level \\cls{}--\\cwm{} gap (adjusted $p{=}0.012$) and function-level \\cls{}--\\traj{} equivalence (adjusted $p{=}0.021$). The repo-level \\cwm{}--\\traj{} comparison does not survive correction (adjusted $p{=}0.078$); we interpret this difference as directionally consistent but not confirmatory.\n\n\\section{Mixed-Effects Regression}\n\\label{app:interaction}\n\nWe fit mixed-effects linear probability models (LPM) to test the formulation$\\times$complexity interaction formally. We choose LPM because coefficients are directly interpretable as probability differences (percentage points), consistent with the reporting units in the main text; at these sample sizes ($n{\\approx}56$K cross-complexity, repo-level pooled cross-model) and base rate range (0.6--0.9), LPM and logistic regression yield identical significance conclusions~\\cite{angrist2009mostly}.\n\n\\paragraph{Cross-complexity model (DeepSeek-Coder).} \\texttt{correct $\\sim$ formulation $\\times$ complexity + (1|problem\\_id)}, $n{=}56{,}480$ observations (\\cls{} + \\cwm{} $\\times$ function + repo), 139 problem clusters. The \\cwm{} main effect at function level is non-significant ($\\hat{\\beta}{=}-0.002$, $z{=}-0.25$, $p{=}0.805$); the \\cwm{}$\\times$repo interaction is highly significant ($\\hat{\\beta}{=}-0.219$, $z{=}-23.7$, $p{<}0.001$). \\cwm{} and \\cls{} are statistically indistinguishable at function level ($\\Delta{=}-0.2$\\pp{}, $p{=}0.805$) but diverge by 22\\pp{} at repo level, confirming the complexity-dependent divergence is not an artifact of aggregation.\n\n\\paragraph{Repo-level cross-model model.} \\texttt{correct $\\sim$ formulation $\\times$ model + (1|problem\\_id)}, both model families, repo level only. \\cwm{} deficit: $\\hat{\\beta}{=}-0.22$ ($-$22\\pp{}, $z{=}-64.4$, $p{<}0.001$). Model effect: +1.1\\pp{} for Qwen3 ($z{=}3.1$, $p{=}0.002$). Formulation$\\times$model interaction: +1.6\\pp{} less \\cwm{} degradation on Qwen3 ($z{=}2.8$, $p{=}0.006$). Formulation explains $>$95\\% of the predictable variance; model identity modulates gap magnitude without changing direction. The 25-cluster random intercept structure limits effective degrees of freedom for the random effects; inferences on fixed effects (formulation, complexity) are robust as they pool across the full observation count.\n\n\\section{CWM Parseable Bias Analysis}\n\\label{app:parseable_bias}\n\nThe default-to-pass assignment for unparseable \\cwm{} outputs is not random with respect to instance difficulty. Unparseable instances have significantly higher pass rates than parseable ones (74.6\\% vs.\\ 68.3\\%, $\\chi^2$ $p = 5.9 \\times 10^{-10}$), and \\cls{} models achieve higher accuracy on unparseable instances (86.4\\% vs.\\ 79.1\\%, $p = 3.3 \\times 10^{-18}$). This indicates that \\cwm{}'s parsing failures concentrate on simpler, pass-heavy instances where the majority-class default happens to be correct more often. Cross-model Jaccard overlap of unparseable instance sets is 0.46, confirming this pattern is instance-driven (specific inputs consistently cause parsing failure across models) rather than stochastic. The net effect is that \\cwm{}'s reported accuracy is inflated by default-correct assignments on easy instances, while its effective discriminative accuracy on harder instances is substantially lower than the aggregate figure suggests.\n\n\n\\section{Threats to Validity (Full Analysis)}\n\\label{app:threats}\n\nWe identify five potential confounds and assess their impact on our conclusions.\n\n\\paragraph{Checkpoint selection.} Val-based selection is unavailable for runs with NaN validation loss (all \\cwm{} repo-level runs, DeepSeek \\cls{} s123), which default to the final epoch checkpoint. A checkpoint ablation on Qwen3-8B \\cls{} s42 quantifies this confound: epoch~1 (ckpt-2200) achieves 85.34\\%, val-selected (ckpt-3600) 84.48\\%, and final epoch (ckpt-6633) 85.29\\%---a $<$1\\pp{} range. The val-selected checkpoint is the lowest, indicating no upward bias from checkpoint selection. The Qwen3-8B \\traj{} comparison (epoch 2: 72.92\\% vs.\\ epoch 3: 70.83\\%) shows a slightly larger ${\\sim}$2\\pp{} shift.\n\n\\paragraph{Evaluation sequence length.} \\cwm{} accuracy varies by ${\\sim}$9\\pp{} across evaluation sequence lengths for the same checkpoint (seq2048: ${\\sim}$65\\% vs.\\ seq4096: ${\\sim}$56\\%), driven by unparseable-rate differences that propagate through majority-class default assignment. \\cls{} is invariant to this parameter. Cross-model \\cwm{} comparisons use different eval lengths (Qwen3: 8192, DeepSeek: 4096) and are not directly comparable in absolute terms. A matched-sequence evaluation shows ${\\sim}$1.5\\pp{} difference for \\cls{} (Appendix~\\ref{app:ablations}), insufficient to explain the 19--26\\pp{} gap. Furthermore, increasing Qwen3-8B \\cwm{} evaluation from seq4096 to seq8192 \\emph{raises} the unparseable rate (63.7\\%$\\to$74\\%) while changing accuracy by only 0.81\\pp{} (64.36\\%$\\to$65.17\\%); giving the model more generation budget worsens format compliance rather than improving it, confirming that format collapse is a structural bottleneck rather than a truncation artifact. Practitioners must standardize evaluation sequence length for generation-based formulations.\n\n\\paragraph{Preprocessing.} DeepSeek \\cls{} accuracy ranges from 82.61\\% (s42, drop preprocessing) to 74.93\\% (s123, truncate preprocessing), a 7.68\\pp{} spread that conflates preprocessing strategy, checkpoint selection method, and seed. The two strategies produce different effective training sets (67,343 vs.\\ 70,748 samples) and different checkpoint selection regimes. The qualitative ranking \\cls{} $>$ \\cwm{} holds under both strategies (Table~\\ref{tab:taxonomy}).\n\n\\paragraph{\\traj{} training regime.} \\traj{} uses a different training configuration: smaller training set (${\\sim}$400 repo-level variants vs.\\ ${\\sim}$70K per-test instances), higher learning rate ($2{\\times}10^{-4}$ vs.\\ $5{\\times}10^{-5}$), and variant-level labels. This asymmetry is inherent to the formulation (trajectory-level labels are only available at variant granularity), but precludes training-data-controlled comparison at repo level. The downsample ablation confirms the \\cls{} formulation advantage persists at matched data volume (80.74\\% vs.\\ 72.92\\%; Appendix~\\ref{app:downsample}), though it controls for training volume but not label granularity (per-test vs.\\ variant-level). Crucially, \\traj{} achieves statistical equivalence with \\cls{} at function level (${\\leq}$1.3\\pp{}, \\S\\ref{sec:func_results}), demonstrating the formulation itself is viable; the repo-level gap is more consistent with data scarcity (${\\sim}$400 variants vs.\\ ${\\sim}$70K per-test instances) than with a formulation-level limitation.\n\n\\paragraph{\\cwm{} scale and pretraining.} Our \\cwm{} baseline uses 4--8B LoRA fine-tuning without execution trace pretraining. The original Code World Model~\\cite{meta2025cwm} uses 32B parameters with mid-training on execution traces, a fundamentally different training regime. At larger scale or with execution-trace pretraining, the generation bottleneck observed here may diminish: larger models produce more coherent long-form outputs, and execution trace exposure may improve output format compliance. This is the primary limitation: all repo-level \\cwm{} conclusions are conditional on the ${\\leq}$8B LoRA regime.\n\nDespite these confounds, the repo-level \\cls{}--\\cwm{} gap (19--26\\pp{}) exceeds any single assessed confound. Even under worst-case compounding (${\\sim}$11.5\\pp{}), the gap retains ${\\geq}$7.5\\pp{} margin; confounds predominantly disadvantage \\cwm{}. However, correlated confounds and limited seed coverage mean definitive causal attribution requires multi-seed replication. At $n{=}48$, the minimum detectable effect (MDE) is ${\\sim}$25\\pp{}~\\cite{hoenig2001}; the \\cls{}--\\cwm{} gap (29--35\\pp{}) exceeds this threshold, while the \\cls{}--\\traj{} gap ($<$10\\pp{}) falls below it, consistent with our TOST equivalence finding. Holm-Bonferroni correction across the four primary comparisons ($k{=}4$) confirms both the \\cls{}--\\cwm{} gap (adjusted $p{=}0.012$) and function-level equivalence (adjusted $p{=}0.021$) survive; the repo-level \\cwm{}--\\traj{} comparison is directionally consistent but does not survive correction (adjusted $p{=}0.078$; Table~\\ref{tab:holm}). The consistent direction across both model families and all tested configurations supports a formulation-level explanation, though definitive causal attribution requires future experiments addressing each confound individually.\n\n\n\\section{Extended Limitations}\n\\label{app:limitations}\n\nThe same-size 4B comparison uses a single seed; \\cls{} 4B seed 123 (val-best ckpt-800) achieves only 75.33\\% test accuracy (+2.4\\pp{} above majority baseline); val-best selection at an early checkpoint (step 800) amplifies the val-test distribution shift observed across all configurations. The \\cwm{} 8B comparison is also single-seed. The validation and test sets have zero problem overlap but differ in mutation type composition (Table~\\ref{tab:mutation_distribution}): \\texttt{operator\\_swap} shifts from 19.1\\% (val) to 34.3\\% (test), the largest single-type distribution mismatch (+15.2\\pp{}). All repo-level results use val-selected checkpoints, and checkpoint selection variance could contribute to observed differences. Our training data is synthetically constructed from mutation operators rather than real developer patches. While mutation testing literature establishes that mutants are reasonable proxies for real faults in test effectiveness studies~\\cite{andrews2005mutation,just2014mutants}, these findings concern mutation \\emph{adequacy} (whether tests that kill mutants also detect real faults), not whether verifiers trained on mutants transfer to real patches. However, the coupling effect underlying these results supports \\emph{relative ranking} validity: a domain shift from synthetic mutations to real bugs may affect absolute accuracy levels, but our core finding---that formulation choice matters at repo level but not function level---concerns relative performance ordering, which is expected to be preserved under distributional shifts that affect all formulations equally. The synthetic-to-real transfer gap for absolute accuracy remains untested. The \\traj{} training configuration differs from \\cls{}/\\cwm{}: smaller training set (${\\sim}$400 vs.\\ ${\\sim}$70K instances), different learning rate ($2{\\times}10^{-4}$ vs.\\ $5{\\times}10^{-5}$), and variant-level evaluation ($n{=}48$ vs.\\ per-test $n{=}9{,}784$). The function-level TOST equivalence ($p = 0.007$, $\\pm$2\\pp{}) is computed on 523 matched variant-level instances across 5 seeds; 2 of 5 seeds use NF4 quantization. Restricting to three bfloat16 seeds yields a comparable mean gap ($-$0.45\\pp{}) but wider confidence interval (df${=}$2); the TOST $p$-value increases from 0.007 to 0.128, which reflects reduced statistical power rather than a shift in the point estimate. The NF4 seeds contribute precision (narrowing the CI) without shifting the mean, consistent with precision being comparable across both quantization levels at function level. Repo-level \\cls{}--\\traj{} comparison is tentative due to configuration and granularity differences.\n",
      "numLines": 464,
      "startLine": 1,
      "totalLines": 464
    }
  },
  "sourceToolAssistantUUID": "89ab2aac-b481-47ea-a6ab-83dcca8575c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-21T15:15:05.434Z_

<details><summary>↩ Tool result · `toolu_01JCZgqSMkXjga26Z3fhHita`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	LLM-based automated program repair systems increasingly rely on test-time compute scaling: generating $K$ candidate patches and selecting the best via a verifier~\cite{snell2024scaling}. Full execution verification is reliable but expensive (\$1--3 per candidate at repository scale\footnote{Based on per-instance costs reported by \citet{yang2024sweagent} and \citet{xia2024agentless}.}), driving demand for execution-free alternatives. Three distinct formulations have emerged for this task: \textbf{generation-based simulation}~\cite{meta2025cwm,maimon2026selfexecution} predicts execution output strings per test; \textbf{trajectory-level scoring}~\cite{shum2025swerm} predicts a binary patch verdict without per-test decomposition; and \textbf{per-test classification}~\cite{ni2023lever,chen2023codet} predicts a pass/fail token per test. Each makes different tradeoffs between diagnostic granularity, output complexity, and inference cost.
5	
6	Despite active development along each axis, no prior work provides a systematic comparison holding model capacity, training data, and compute constant. Practitioners choosing a formulation for their verification pipeline must rely on results from different models, different datasets, and different evaluation protocols. Whether one formulation is uniformly preferable, or whether the choice depends on properties of the code being verified, remains an open empirical question. A related question is whether formulation choice matters at all relative to more basic decisions: at what complexity level does fine-tuning become necessary, and does formulation selection add value beyond what fine-tuning alone provides?
7	
8	We present the first systematic empirical comparison across two representative code LLM families (Qwen3, DeepSeek-Coder), two complexity levels (function-level and repository-level), and multiple seeds. Our contribution is primarily methodological: a matched experimental framework that isolates formulation effects from confounding variables. The analysis also produces actionable outputs: a failure mode taxonomy that characterizes when and why each formulation fails (\S\ref{sec:repo}), error complementarity findings with practical ensemble implications (\S\ref{sec:analysis}), and formulation selection recommendations conditioned on code complexity (\S\ref{sec:conclusion}). The results reveal a three-layer structure. Fine-tuning is necessary (0-shot$\to$fine-tuned gains of 35--36\pp{} at repo level). After fine-tuning, \emph{formulation choice is governed by code complexity}: at function level, all formulations achieve comparable accuracy---consistent with the theoretical analysis in \S\ref{sec:failure-modes}, which predicts that short outputs minimize generation-specific failures. At repository level under our ${\leq}$8B LoRA protocol, this equivalence collapses; variant-level analysis reveals three distinct failure modes consistent across model families, though gap magnitude depends on multiple confounds (\S\ref{sec:threats}). Figure~\ref{fig:reformulation} illustrates the three formulations.
9	
10	We make the following contributions:
11	
12	\begin{itemize}[leftmargin=*,itemsep=2pt]
13	\item \textbf{Formulation near-equivalence at low complexity.} At function level, \cls{} and \cwm{} achieve statistical equivalence across two representative code LLM families; \traj{} reaches parity on Qwen3 but exceeds the equivalence margin on DeepSeek-Coder. Per-test classification matches trajectory-level accuracy while identifying which tests fail (\S\ref{sec:func_results}, \S\ref{sec:equivalence}).
14	
15	\item \textbf{Complexity-dependent divergence.} A robust interaction ($z{=}-23.7$, $n{=}56{,}480$) confirms that formulations equivalent at function level (${\leq}$1.3\pp{}) diverge by 19--26\pp{} at repository level under ${\leq}$8B LoRA fine-tuning, driven by format collapse---four targeted interventions all fail to close the gap (Appendix~\ref{app:extended_analysis}(g)). Variant-level analysis reveals three failure modes consistent across model families, though gap magnitude depends on single-seed evaluation and multiple confounds (\S\ref{sec:repo}, \S\ref{sec:threats}).
16	
17	\item \textbf{Error complementarity.} \cls{} and \cwm{} exhibit partially complementary error patterns at function level (oracle: 90.63\%; single-seed); at repo level, oracle routing reaches 95.83\% variant accuracy (+14.58\pp{}; single-seed), the strongest practical argument for exploring the formulation design space (\S\ref{sec:analysis}).
18	\end{itemize}
19	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e320c838-a663-4e7c-a5b8-68350f2ea649",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "3c4b767c-926c-4eef-b36f-962627215834",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nLLM-based automated program repair systems increasingly rely on test-time compute scaling: generating $K$ candidate patches and selecting the best via a verifier~\\cite{snell2024scaling}. Full execution verification is reliable but expensive (\\$1--3 per candidate at repository scale\\footnote{Based on per-instance costs reported by \\citet{yang2024sweagent} and \\citet{xia2024agentless}.}), driving demand for execution-free alternatives. Three distinct formulations have emerged for this task: \\textbf{generation-based simulation}~\\cite{meta2025cwm,maimon2026selfexecution} predicts execution output strings per test; \\textbf{trajectory-level scoring}~\\cite{shum2025swerm} predicts a binary patch verdict without per-test decomposition; and \\textbf{per-test classification}~\\cite{ni2023lever,chen2023codet} predicts a pass/fail token per test. Each makes different tradeoffs between diagnostic granularity, output complexity, and inference cost.\n\nDespite active development along each axis, no prior work provides a systematic comparison holding model capacity, training data, and compute constant. Practitioners choosing a formulation for their verification pipeline must rely on results from different models, different datasets, and different evaluation protocols. Whether one formulation is uniformly preferable, or whether the choice depends on properties of the code being verified, remains an open empirical question. A related question is whether formulation choice matters at all relative to more basic decisions: at what complexity level does fine-tuning become necessary, and does formulation selection add value beyond what fine-tuning alone provides?\n\nWe present the first systematic empirical comparison across two representative code LLM families (Qwen3, DeepSeek-Coder), two complexity levels (function-level and repository-level), and multiple seeds. Our contribution is primarily methodological: a matched experimental framework that isolates formulation effects from confounding variables. The analysis also produces actionable outputs: a failure mode taxonomy that characterizes when and why each formulation fails (\\S\\ref{sec:repo}), error complementarity findings with practical ensemble implications (\\S\\ref{sec:analysis}), and formulation selection recommendations conditioned on code complexity (\\S\\ref{sec:conclusion}). The results reveal a three-layer structure. Fine-tuning is necessary (0-shot$\\to$fine-tuned gains of 35--36\\pp{} at repo level). After fine-tuning, \\emph{formulation choice is governed by code complexity}: at function level, all formulations achieve comparable accuracy---consistent with the theoretical analysis in \\S\\ref{sec:failure-modes}, which predicts that short outputs minimize generation-specific failures. At repository level under our ${\\leq}$8B LoRA protocol, this equivalence collapses; variant-level analysis reveals three distinct failure modes consistent across model families, though gap magnitude depends on multiple confounds (\\S\\ref{sec:threats}). Figure~\\ref{fig:reformulation} illustrates the three formulations.\n\nWe make the following contributions:\n\n\\begin{itemize}[leftmargin=*,itemsep=2pt]\n\\item \\textbf{Formulation near-equivalence at low complexity.} At function level, \\cls{} and \\cwm{} achieve statistical equivalence across two representative code LLM families; \\traj{} reaches parity on Qwen3 but exceeds the equivalence margin on DeepSeek-Coder. Per-test classification matches trajectory-level accuracy while identifying which tests fail (\\S\\ref{sec:func_results}, \\S\\ref{sec:equivalence}).\n\n\\item \\textbf{Complexity-dependent divergence.} A robust interaction ($z{=}-23.7$, $n{=}56{,}480$) confirms that formulations equivalent at function level (${\\leq}$1.3\\pp{}) diverge by 19--26\\pp{} at repository level under ${\\leq}$8B LoRA fine-tuning, driven by format collapse---four targeted interventions all fail to close the gap (Appendix~\\ref{app:extended_analysis}(g)). Variant-level analysis reveals three failure modes consistent across model families, though gap magnitude depends on single-seed evaluation and multiple confounds (\\S\\ref{sec:repo}, \\S\\ref{sec:threats}).\n\n\\item \\textbf{Error complementarity.} \\cls{} and \\cwm{} exhibit partially complementary error patterns at function level (oracle: 90.63\\%; single-seed); at repo level, oracle routing reaches 95.83\\% variant accuracy (+14.58\\pp{}; single-seed), the strongest practical argument for exploring the formulation design space (\\S\\ref{sec:analysis}).\n\\end{itemize}\n",
      "numLines": 19,
      "startLine": 1,
      "totalLines": 19
    }
  },
  "sourceToolAssistantUUID": "e320c838-a663-4e7c-a5b8-68350f2ea649",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-21T15:15:05.901Z_

<details open><summary>🔧 Tool call — Read · `toolu_013YRPRSsLmH2vmU7pND6Lzs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c4b767c-926c-4eef-b36f-962627215834",
  "isSidechain": false,
  "requestId": "req_011CbFw5LBrLTbgAZViyq7fK",
  "type": "assistant",
  "uuid": "976d33ca-7007-458d-a7aa-e6e6d58cfb5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011DoB1jz7aNEmrxedrFHCwQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13336,
      "cache_read_input_tokens": 11447,
      "output_tokens": 337,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 337,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 13336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13336
          },
          "type": "message"
        }
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

_source line 16 · 2026-05-21T15:15:05.907Z_

<details><summary>↩ Tool result · `toolu_013YRPRSsLmH2vmU7pND6Lzs`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We systematically compare \cls{}, \cwm{}, and \traj{} across two representative code LLM families, two complexity levels, and multiple seeds to characterize the formulation design space for neural code verification.
5	
6	\subsection{Experimental Setup}
7	\label{sec:setup}
8	
9	\paragraph{Datasets.}
10	\emph{Function-level}: mutated variants from HumanEval~\cite{chen2021humaneval} and MBPP~\cite{austin2021mbpp} (five mutation types), labels verified by execution. 19,076 samples (train 15,290 / val 1,896 / test 1,890; pass:fail $\approx$ 52:48, majority baseline 51.75\%).
11	\emph{Repo-level}: per-test instances from SWE-bench Verified~\cite{chowdhury2024swebenchverified} mutants. ${\sim}$70K training samples; val ($n{=}9{,}335$) and test ($n{=}9{,}784$) have zero problem overlap (majority baseline 72.96\%). Val-based checkpoint selection follows standard practice~\cite{jimenez2024swebench} where validation loss is computable; runs using truncate preprocessing produce NaN validation loss due to length-mismatched sequences, which defaults to the final epoch checkpoint (affects DeepSeek \cls{} s123, all \cwm{} runs, and Qwen3 \traj{} runs; see Appendix~\ref{app:hyperparams}).
12	
13	\paragraph{Models and training.}
14	We fine-tune Qwen3-4B and Qwen3-8B~\cite{qwen2025qwen3} with Low-Rank Adaptation (LoRA)~\cite{hu2022lora} (rank 16, 3 epochs) across five seeds. Seeds 42/123/456 use bfloat16; seeds 789/0 use NormalFloat 4-bit (NF4) quantization~\cite{dettmers2024qlora} to test robustness to precision reduction (function-level accuracy remains within seed noise across both precisions; see footnote in \S\ref{sec:equivalence}). As a cross-model consistency check, we additionally fine-tune DeepSeek-Coder-6.7B~\cite{guo2024deepseekcoder} with identical LoRA configuration (2 seeds each for \cls{} and \cwm{}). Our \cwm{} baseline is a LoRA fine-tuned variant for matched comparison, not a reproduction of the 32B Code World Model~\cite{meta2025cwm}. Repo-level models use val-selected checkpoints where available; runs with NaN validation loss use the final epoch checkpoint (Appendix~\ref{app:hyperparams}). Zero-shot baselines use Qwen3-8B and Qwen3-32B (NF4) as LLM-as-judge. Full hyperparameter details appear in Appendix~\ref{app:hyperparams}.
15	
16	\paragraph{Statistics.}
17	Confidence intervals use clustered bootstrap~\cite{davison1997bootstrap} (114 problem clusters, 10K resamples; we resample entire problems, not individual tests, to preserve within-problem correlations); per-test vs.\ trajectory-level equivalence uses Two One-Sided Tests (TOST)~\cite{schuirmann1987tost} with $\pm$2 percentage point (\pp{}) margin. Holm-Bonferroni correction~\cite{holm1979} controls family-wise error rate across the four primary comparisons (Table~\ref{tab:holm}). Intraclass correlation coefficient (ICC)~\cite{shrout1979icc} quantifies within-problem correlation. Oracle analysis uses SWE-bench Verified (500 instances).
18	
19	
20	\subsection{Function-Level Results}
21	\label{sec:func_results}
22	
23	Table~\ref{tab:main_results} reports function-level results across formulations and model families.
24	
25	\begin{table}[t]
26	\centering
27	\small
28	\caption{Function-level per-test accuracy on HumanEval+MBPP ($n{=}1{,}890$). Mean $\pm$ std over seeds. Seeds 42/123/456: bfloat16; 789/0: NF4. DeepSeek: $n{=}2$ seeds; std reported for descriptive comparison, not inferential. \traj{} evaluated on 1,032-sample subset (447 matched variants).}
29	\label{tab:main_results}
30	\resizebox{\columnwidth}{!}{%
31	\setlength{\tabcolsep}{4pt}
32	\begin{tabular}{llcc}
33	\toprule
34	\textbf{Method} & \textbf{Model} & \textbf{Seeds} & \textbf{Accuracy (\%)} \\
35	\midrule
36	\multicolumn{4}{l}{\emph{Qwen3 (primary)}} \\
37	\cls{} (fine-tuned) & 4B & 5 & \textbf{88.43 $\pm$ 0.78} \\
38	\cwm{} (fine-tuned) & 4B & 5 & \underline{87.19 $\pm$ 0.37} \\
39	\traj{} (fine-tuned) & 4B & 5 & 86.30 $\pm$ 0.97 \\
40	\midrule
41	\multicolumn{4}{l}{\emph{DeepSeek-Coder (cross-model consistency check)}} \\
42	\cls{} (fine-tuned) & 6.7B & 2 & \textbf{86.85 $\pm$ 0.11} \\
43	\cwm{} (fine-tuned) & 6.7B & 2 & \underline{86.83 $\pm$ 1.49} \\
44	\traj{} (fine-tuned) & 6.7B & 2 & 84.16 $\pm$ 1.30 \\
45	\midrule
46	\multicolumn{4}{l}{\emph{Prompting baselines}} \\
47	0-shot & 8B (Qwen3) & 1 & 68.70 \\
48	0-shot & 6.7B (DeepSeek) & 1 & 63.00 \\
49	ZS LLM-as-judge & 8B (Qwen3) & 1 & 64.40 \\
50	ZS LLM-as-judge & 6.7B (DeepSeek) & 1 & 56.56 \\
51	ZS LLM-as-judge & 32B (NF4) & 1 & 71.69 \\
52	3-shot ICL & 8B (Qwen3) & 1 & 68.78 \\
53	3-shot ICL & 6.7B (DeepSeek) & 1 & 59.95 \\
54	\midrule
55	Majority (pass) & --- & --- & 51.75 \\
56	\bottomrule
57	\end{tabular}}
58	\end{table}
59	
60	All three formulations achieve comparable accuracy on Qwen3-4B: \cls{} 88.43\% ($\pm$0.78), \cwm{} 87.19\% ($\pm$0.37), \traj{} 86.30\% ($\pm$0.97). DeepSeek-Coder-6.7B shows: \cls{} 86.85\%, \cwm{} 86.83\%, \traj{} 84.16\%. The \cls{}--\cwm{} gap (0.02--1.24\pp{}) is within seed noise in both families. However, the \cls{}--\traj{} gap is model-dependent: $<$1\pp{} on Qwen3 but 2.69\pp{} on DeepSeek-Coder, exceeding the $\pm$2\pp{} equivalence margin (\S\ref{sec:equivalence}). \cls{} and \cwm{} are robustly equivalent; \traj{} parity is model-contingent. Zero-shot baselines (Tables~\ref{tab:main_results} and~\ref{tab:repo_level}) establish that repo-level verification requires fine-tuning (0-shot$\to$fine-tuned gains of 35--36\pp{}) and that formulation choice matters only at repo level (\cls{} outperforms \cwm{} by 19--26\pp{}).
61	
62	
63	\subsection{Scaling Behavior}
64	\label{sec:scaling}
65	
66	Beyond overall accuracy, we examine whether formulation ranking is stable across model sizes. Table~\ref{tab:scaling} compares all three formulations at 4B and 8B using seeds 42 and 123 in full bfloat16 precision (excluding NF4 seeds to isolate the size effect).
67	
68	\begin{table}[t]
69	\centering
70	\small
71	\caption{Model-size scaling: accuracy (\%) at 4B and 8B (Qwen3, seeds 42/123, full bfloat16 precision). \cls{} and \traj{} scale positively; \cwm{} does not.}
72	\label{tab:scaling}
73	\setlength{\tabcolsep}{4pt}
74	\begin{tabular}{llcccc}
75	\toprule
76	\textbf{Method} & \textbf{Size} & \textbf{s42} & \textbf{s123} & \textbf{Mean} & \textbf{$\Delta$ 4B$\to$8B} \\
77	\midrule
78	\cls{} & 4B & 87.83 & 89.52 & \textbf{88.68} & \multirow{2}{*}{+1.27} \\
79	\cls{} & 8B & \textbf{90.48} & 89.40 & \textbf{89.94} & \\
80	\midrule
81	\cwm{} & 4B & 87.51 & 87.20 & \underline{87.36} & \multirow{2}{*}{$-$0.03} \\
82	\cwm{} & 8B & 87.67 & 86.98 & 87.33 & \\
83	\midrule
84	\traj{} & 4B & 85.66 & 85.47 & 85.57 & \multirow{2}{*}{+2.13} \\
85	\traj{} & 8B & 87.60 & 87.79 & \underline{87.70} & \\
86	\bottomrule
87	\end{tabular}
88	\end{table}
89	
90	\cls{} and \traj{} both scale positively from 4B to 8B (+1.27\pp{} and +2.13\pp{} respectively), while \cwm{} remains flat ($-$0.03\pp{}). At 8B, the ranking is \cls{} (89.94) $>$ \traj{} (87.70) $>$ \cwm{} (87.33). The \cls{}--\cwm{} gap widens from 1.32\pp{} at 4B to 2.62\pp{} at 8B (Figure~\ref{fig:scaling_gap}); clustered bootstrap on the 3-seed superset (42, 123, 456 for \cls{}/\cwm{}) yields $p = 0.0066$ (95\% CI $[1.80, 2.71]$), which confirms the widening is not a sampling artifact.
91	
92	\cwm{} flat scaling ($-$0.03\pp{}) may reflect suboptimal hyperparameter transfer at 8B rather than a fundamental limitation; we do not claim generation \emph{cannot} benefit from scale. At function level, outputs are short (integers, booleans) and format compliance is near-perfect; at repo level, output length grows to ${\sim}$477 tokens on average, and the same generation bottleneck manifests as format collapse (51--74\% unparseable; \S\ref{sec:repo}). \traj{} also shows no scaling benefit at repo level (72.92\% at both 4B and 8B); only \cls{} scales positively across both complexity levels.
93	
94	
95	\subsection{Per-Test vs.\ Trajectory-Level Equivalence}
96	\label{sec:equivalence}
97	
98	We compare \cls{} (aggregated via all-pass rule) against \traj{} on 523 variant-level instances across five seeds.\footnote{Seeds 789 and 0 use NF4 quantized inference; the remaining three use bfloat16. Restricting to bfloat16 seeds only (3 seeds) yields $p{=}0.128$: consistent in direction but underpowered due to reduced seed coverage.} The pooled gap is $-$0.45\pp{} (95\% CI [$-$1.71, +0.84]); the TOST equivalence test confirms statistical equivalence at $p = 0.007$ ($\pm$2\pp{} margin, Holm-Bonferroni corrected). Our $\pm$2\pp{} threshold follows the SESOI framework~\cite{lakens2017}, set independently of the observed gap and grounded in deployment relevance: at function-level accuracy (85--88\%), a 2\pp{} difference corresponds to ${\sim}$38 per-test predictions across 1,890 tests (${\sim}$2--3 problems out of 114)---comparable to between-seed variation (0.37--0.97\pp{} std, Table~\ref{tab:main_results}) and checkpoint selection noise ($<$1\pp{}, \S\ref{sec:threats}). A difference within this range is indistinguishable from training noise for pipeline selection decisions. Equivalence holds at margins as tight as $\pm$1.52\pp{} (Table~\ref{tab:tost_sensitivity}), well below the pre-specified threshold. Within-problem predictions are correlated (intraclass correlation ICC $= 0.191$, $p < 0.0001$, design effect (DEFF) $= 3.97$); all statistical tests use clustered bootstrap accordingly. On DeepSeek-Coder, the observed \cls{}--\cwm{} gap of 0.02\pp{} is consistent with equivalence, but with only 2 seeds the comparison is underpowered. The DeepSeek \cls{}--\traj{} gap (2.69\pp{}) exceeds the $\pm$2\pp{} margin; \traj{} parity is model-dependent rather than universal, while the \cls{}--\cwm{} equivalence is robust across both families. Per-test classification provides diagnostic information (which specific tests fail) at no cost to variant-level accuracy. This parallels process supervision~\cite{lightman2023letsverify}: step-level verification enables error localization without accuracy loss.
99	
100	Oracle analysis on SWE-bench Verified (500 instances) shows that per-test advantage concentrates at $T \geq 2$ fail-to-pass tests (31.3\% of instances, contributing 55.3\% of the total oracle advantage; Appendix~\ref{app:oracle}).
101	
102	
103	\subsection{Repo-Level: Complexity-Dependent Divergence}
104	\label{sec:repo}
105	
106	Table~\ref{tab:repo_level} compares formulations at repository-level complexity. Variant-level comparisons rely on limited seed coverage; the per-test interaction effect is statistically confirmed (see below). Checkpoints are val-selected where validation loss is computable (\S\ref{sec:setup}); the test set has zero problem overlap with validation.
107	
108	\begin{table}[t]
109	\centering
110	\small
111	\caption{Repo-level cross-formulation comparison on SWE-bench Verified test set. Qwen3-8B \cls{}/\traj{}: mean $\pm$ std over 3 seeds; DeepSeek \cls{}: 2 seeds\textsuperscript{$\ddagger$}; DeepSeek \traj{}: 3 seeds; Qwen3-4B: seed 42. \cwm{} multi-seed runs in progress.}
112	\label{tab:repo_level}
113	\resizebox{\columnwidth}{!}{%
114	\setlength{\tabcolsep}{4pt}
115	\begin{tabular}{lcccc}
116	\toprule
117	\textbf{Model} & \textbf{\cls{} (\%)} & \textbf{\cls{} Var.\ (\%)} & \textbf{\cwm{} (\%)} & \textbf{\traj{} Var.\ (\%)\textsuperscript{$\diamond$}} \\
118	\midrule
119	Qwen3-4B & 83.63 & 64.58 & 58.04 & 72.92 \\
120	Qwen3-8B & \textbf{84.83 $\pm$ 0.67} & 72.92 / 81.25\textsuperscript{$\dagger$} & \tbd{} & 72.91 $\pm$ 3.61 \\
121	DeepSeek-6.7B & 84.38 $\pm$ 2.50\textsuperscript{$\ddagger$} & 81.25\textsuperscript{$\dagger$} & \tbd{} & 77.08 $\pm$ 3.61 \\
122	\midrule
123	0-shot (Qwen3-8B) & 49.90 & --- & --- & --- \\
124	0-shot (DeepSeek) & 48.54 & --- & --- & --- \\
125	Majority & 72.96 & 54.17 & 72.96 & 54.17 \\
126	\bottomrule
127	\end{tabular}}
128	
129	\vspace{2pt}
130	{\footnotesize \textsuperscript{$\dagger$}Individual-seed variant accuracy; multi-seed aggregate pending. \textsuperscript{$\ddagger$}One seed excluded: truncate preprocessing$\to$NaN val loss, decision collapse (Table~\ref{tab:taxonomy}); mean over two matched seeds. \textsuperscript{$\diamond$}Var.\ columns: variant-level accuracy ($n{=}48$); \cls{} aggregated via all-pass rule; \traj{} by design. Per-test: $n{=}9{,}784$. \cwm{} unparseable: 54\% (4B); default to pass; parseable-only 38--43\%, below majority. Eval seq\_length differs across models (Appendix~\ref{app:threats}). \cwm{} uses epoch-3 checkpoint (val loss undefined); see text for checkpoint sensitivity analysis.}
131	\end{table}
132	
133	Zero-shot prompting collapses to an always-predict-unresolved baseline (variant accuracy 45.83\%, below majority 54.17\%; Appendix~\ref{app:few_shot}).
134	
135	\paragraph{Formulation divergence (single-seed).} Under our 4--8B LoRA protocol, \cls{} and \cwm{} diverge on Qwen3: the gap is 25.59\pp{} at 4B (\cls{} 83.63\% vs.\ \cwm{} 58.04\%, seed 42; Figure~\ref{fig:scaling_gap}) and 19.31\pp{} at 8B (84.48\% vs.\ 65.17\%). \cwm{} falls below majority baseline at both scales. These gaps suggest complexity-dependent formulation effectiveness, though single-seed design and multiple confounds (\S\ref{sec:threats}) preclude definitive causal attribution.
136	
137	\paragraph{Cross-model consistency.} DeepSeek-Coder shows the same direction (\cls{} $>$ \cwm{}) under single-seed constraints. DeepSeek \cls{} degradation ranges from ${\sim}$4\pp{} (s42, drop preprocessing) to ${\sim}$12\pp{} (s123, truncate preprocessing), reflecting preprocessing and checkpoint selection sensitivity (Table~\ref{tab:taxonomy}). The \cls{}--\cwm{} gap magnitude also varies across families (20\pp{} for Qwen3 vs.\ 23--28\pp{} for DeepSeek), primarily reflecting checkpoint selection: DeepSeek \cwm{}'s val-selected checkpoint (56.70\%) underperforms its epoch-3 checkpoint (61.49\%), widening the apparent gap. Under matched checkpoint selection (epoch~3 for both), the cross-model gap difference narrows to ${\sim}$2\pp{} (Qwen3: 20.47\pp{} vs.\ DeepSeek: 22.89\pp{}). The gap is formulation-driven rather than model-specific. Eval seq\_length differs between models (Appendix~\ref{app:threats}).
138	
139	\paragraph{Failure mode taxonomy.} Variant-level analysis ($n{=}48$, Appendix Table~\ref{tab:variant_level}) reveals three failure modes (Table~\ref{tab:taxonomy}): format collapse (\cwm{}, 51--74\% unparseable), decision collapse (\cls{} under truncate preprocessing, fail recall ${\sim}$14\%), and aggregation penalty (\cls{} under drop preprocessing, fail recall 38--57\%). Decision collapse is configuration-dependent, not model-inherent. \traj{} avoids aggregation penalty by predicting variant outcomes directly (72.91--77.08\%). Downsampling \cls{} training data to match \traj{}'s data volume yields 80.74\%, still 7.82\pp{} above \traj{}; this controls data volume but not label granularity (per-test vs.\ variant-level), and remains a single-seed comparison (Appendix~\ref{app:downsample}).
140	
141	\begin{table}[t]
142	\centering
143	\small
144	\caption{Repo-level failure mode taxonomy. Variant-level majority baseline: 54.17\%.}
145	\label{tab:taxonomy}
146	\setlength{\tabcolsep}{3pt}
147	\resizebox{\columnwidth}{!}{%
148	\begin{tabular}{llcc}
149	\toprule
150	\textbf{Failure Mode} & \textbf{Representative} & \textbf{Fail Recall} & \textbf{Variant Acc} \\
151	\midrule
152	Format collapse & \cwm{} (all) & N/A & 48--52\% \\
153	Decision collapse & \cls{} (DeepSeek, s123) & ${\sim}$14\% & 56\% \\
154	Aggr.\ penalty & \cls{} (Qwen3-8B) & 51--57\% & 73--81\% \\
155	Aggr.\ penalty & \cls{} (DeepSeek, s42) & 38--51\% & 79--81\% \\
156	\bottomrule
157	\end{tabular}}
158	\end{table}
159	
160	\paragraph{Default assignment artifact.} The apparent \cwm{} accuracy increase from 4B to 8B is an artifact of rising unparseable rate (53.7\%$\to$73.8\%), which inflates accuracy via majority-class default while parseable-only accuracy decreases (42.88\%$\to$38.52\%; Appendix~\ref{app:parseable_bias}).
161	
162	\paragraph{Complexity as moderator.} The \cls{}--\cwm{} gap widens from 1--3\pp{} (function) to 19--26\pp{} (repo) under our protocol; a matched-context ablation confirms input disparity explains $<$3\% of this gap (Appendix~\ref{app:ablations}).
163	
164	\paragraph{Formulation$\times$complexity interaction.} A mixed-effects linear probability model with problem-level random intercepts ($n{=}56{,}480$ observations, 139 problem clusters, DeepSeek-Coder) confirms the interaction: the \cwm{} effect at function level is negligible ($\hat{\beta}{=}-0.002$, $p{=}0.805$), but the formulation$\times$complexity interaction is highly significant ($z{=}-23.7$, $p{<}0.001$). \cwm{} and \cls{} are statistically indistinguishable at function level ($\Delta{=}-0.2$\pp{}) but diverge by 22\pp{} at repo level, confirming the divergence is not an artifact of aggregation. The cross-complexity analysis uses DeepSeek-Coder, the only family with both function- and repo-level \cwm{} evaluations under matched conditions. Across both model families at repo level, the \cwm{} deficit is $-$22\pp{} ($z{=}-64.4$, $p{<}0.001$); the model family effect is significant but small (+1.1\pp{} for Qwen3, $p{=}0.002$), and the formulation$\times$model interaction is likewise small (+1.6\pp{}, $p{=}0.006$). Formulation explains $>$95\% of the predictable variance; model identity modulates gap magnitude without changing direction (Appendix~\ref{app:interaction}).
165	
166	Additional repo-level limitations appear in Appendix~\ref{app:limitations}.
167	
168	
169	\subsection{Analysis}
170	\label{sec:analysis}
171	
172	\paragraph{Aggregation penalty.} Under the all-pass rule, a single false negative flips the variant verdict. The penalty ranges from 1.36\pp{} (DeepSeek s42) to 19\pp{} (Qwen3-4B), depending on fail recall and test count (Appendix Table~\ref{tab:variant_level}). Val-based checkpoint selection biases toward per-test accuracy at the expense of fail recall, which amplifies the penalty. \traj{} avoids this by predicting variant outcomes directly (72.91--77.08\%). The penalty is predictable from test count: function-level variants ($\bar{T} \approx 2.3$) incur negligible penalty, while repo-level variants ($\bar{T} \gg 10$) incur substantial penalty, both the \emph{advantage} and \emph{cost} of per-test granularity concentrate at high $T$ (Appendix~\ref{app:extended_analysis}(a)).
173	
174	\paragraph{Why does generation degrade at repo level?} Output space complexity increases nonlinearly: function-level outputs are short strings (integers, booleans); repo-level outputs are unconstrained execution traces (mean ${\sim}$477 tokens) where errors compound multiplicatively, and cause format collapse (53--74\% unparseable). Even among parseable outputs, accuracy (38--43\%) is below majority baseline, which indicates a semantic gap beyond format compliance (Appendix~\ref{app:qualitative}).
175	
176	\cls{} achieves 217$\times$ higher throughput than \cwm{} (1 output token vs.\ avg 477), consistent across both model families.
177	
178	\paragraph{Error complementarity.} At function level, \cls{} and \cwm{} exhibit partial complementarity: both are FP-dominant (over-predict failure), but at different rates (\cls{} 56.5\%, \cwm{} 70.3\%; Appendix~\ref{app:extended_analysis}(a)), so \cwm{} over-predicts failure on instances \cls{} correctly classifies. An oracle combination achieves 90.63\% (+2.80\pp{} over the best single formulation; single-seed estimate). At repo level, oracle routing across configurations reaches 95.83\% variant accuracy (+14.58\pp{} over the best single configuration, $n{=}48$), the strongest evidence that the formulation design space contains complementary solutions worth exploring. A re-repair pilot found no benefit from per-test diagnostics ($n{=}44$, $p{=}0.42$; Appendix~\ref{app:extended_analysis}(j)). Extended analysis appears in Appendix~\ref{app:extended_analysis}.
179	
180	\subsection{Threats to Validity}
181	\label{sec:threats}
182	
183	We identify five potential confounds and assess each in Appendix~\ref{app:threats}: checkpoint selection ($<$1\pp{} variation in ablation; NaN validation loss forces final-epoch default in all \cwm{} runs and DeepSeek \cls{} s123), evaluation sequence length (${\sim}$1.5\pp{}), preprocessing (${\sim}$8\pp{} cross-configuration variance), \traj{} training regime (downsample confirms formulation advantage), and \cwm{} scale/pretraining (primary limitation; all repo-level \cwm{} conclusions conditional on the ${\leq}$8B LoRA regime). The 19--26\pp{} gap exceeds any single assessed confound, but correlated confounds and limited seeds mean definitive causal attribution requires multi-seed replication. Holm-Bonferroni correction confirms the two core claims survive (adjusted $p{=}0.012$ and $p{=}0.021$; Table~\ref{tab:holm}).
184	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "976d33ca-7007-458d-a7aa-e6e6d58cfb5a",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "634f9a5c-c9f4-4a99-879d-20b041668733",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe systematically compare \\cls{}, \\cwm{}, and \\traj{} across two representative code LLM families, two complexity levels, and multiple seeds to characterize the formulation design space for neural code verification.\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\n\\paragraph{Datasets.}\n\\emph{Function-level}: mutated variants from HumanEval~\\cite{chen2021humaneval} and MBPP~\\cite{austin2021mbpp} (five mutation types), labels verified by execution. 19,076 samples (train 15,290 / val 1,896 / test 1,890; pass:fail $\\approx$ 52:48, majority baseline 51.75\\%).\n\\emph{Repo-level}: per-test instances from SWE-bench Verified~\\cite{chowdhury2024swebenchverified} mutants. ${\\sim}$70K training samples; val ($n{=}9{,}335$) and test ($n{=}9{,}784$) have zero problem overlap (majority baseline 72.96\\%). Val-based checkpoint selection follows standard practice~\\cite{jimenez2024swebench} where validation loss is computable; runs using truncate preprocessing produce NaN validation loss due to length-mismatched sequences, which defaults to the final epoch checkpoint (affects DeepSeek \\cls{} s123, all \\cwm{} runs, and Qwen3 \\traj{} runs; see Appendix~\\ref{app:hyperparams}).\n\n\\paragraph{Models and training.}\nWe fine-tune Qwen3-4B and Qwen3-8B~\\cite{qwen2025qwen3} with Low-Rank Adaptation (LoRA)~\\cite{hu2022lora} (rank 16, 3 epochs) across five seeds. Seeds 42/123/456 use bfloat16; seeds 789/0 use NormalFloat 4-bit (NF4) quantization~\\cite{dettmers2024qlora} to test robustness to precision reduction (function-level accuracy remains within seed noise across both precisions; see footnote in \\S\\ref{sec:equivalence}). As a cross-model consistency check, we additionally fine-tune DeepSeek-Coder-6.7B~\\cite{guo2024deepseekcoder} with identical LoRA configuration (2 seeds each for \\cls{} and \\cwm{}). Our \\cwm{} baseline is a LoRA fine-tuned variant for matched comparison, not a reproduction of the 32B Code World Model~\\cite{meta2025cwm}. Repo-level models use val-selected checkpoints where available; runs with NaN validation loss use the final epoch checkpoint (Appendix~\\ref{app:hyperparams}). Zero-shot baselines use Qwen3-8B and Qwen3-32B (NF4) as LLM-as-judge. Full hyperparameter details appear in Appendix~\\ref{app:hyperparams}.\n\n\\paragraph{Statistics.}\nConfidence intervals use clustered bootstrap~\\cite{davison1997bootstrap} (114 problem clusters, 10K resamples; we resample entire problems, not individual tests, to preserve within-problem correlations); per-test vs.\\ trajectory-level equivalence uses Two One-Sided Tests (TOST)~\\cite{schuirmann1987tost} with $\\pm$2 percentage point (\\pp{}) margin. Holm-Bonferroni correction~\\cite{holm1979} controls family-wise error rate across the four primary comparisons (Table~\\ref{tab:holm}). Intraclass correlation coefficient (ICC)~\\cite{shrout1979icc} quantifies within-problem correlation. Oracle analysis uses SWE-bench Verified (500 instances).\n\n\n\\subsection{Function-Level Results}\n\\label{sec:func_results}\n\nTable~\\ref{tab:main_results} reports function-level results across formulations and model families.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Function-level per-test accuracy on HumanEval+MBPP ($n{=}1{,}890$). Mean $\\pm$ std over seeds. Seeds 42/123/456: bfloat16; 789/0: NF4. DeepSeek: $n{=}2$ seeds; std reported for descriptive comparison, not inferential. \\traj{} evaluated on 1,032-sample subset (447 matched variants).}\n\\label{tab:main_results}\n\\resizebox{\\columnwidth}{!}{%\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Method} & \\textbf{Model} & \\textbf{Seeds} & \\textbf{Accuracy (\\%)} \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{Qwen3 (primary)}} \\\\\n\\cls{} (fine-tuned) & 4B & 5 & \\textbf{88.43 $\\pm$ 0.78} \\\\\n\\cwm{} (fine-tuned) & 4B & 5 & \\underline{87.19 $\\pm$ 0.37} \\\\\n\\traj{} (fine-tuned) & 4B & 5 & 86.30 $\\pm$ 0.97 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{DeepSeek-Coder (cross-model consistency check)}} \\\\\n\\cls{} (fine-tuned) & 6.7B & 2 & \\textbf{86.85 $\\pm$ 0.11} \\\\\n\\cwm{} (fine-tuned) & 6.7B & 2 & \\underline{86.83 $\\pm$ 1.49} \\\\\n\\traj{} (fine-tuned) & 6.7B & 2 & 84.16 $\\pm$ 1.30 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{Prompting baselines}} \\\\\n0-shot & 8B (Qwen3) & 1 & 68.70 \\\\\n0-shot & 6.7B (DeepSeek) & 1 & 63.00 \\\\\nZS LLM-as-judge & 8B (Qwen3) & 1 & 64.40 \\\\\nZS LLM-as-judge & 6.7B (DeepSeek) & 1 & 56.56 \\\\\nZS LLM-as-judge & 32B (NF4) & 1 & 71.69 \\\\\n3-shot ICL & 8B (Qwen3) & 1 & 68.78 \\\\\n3-shot ICL & 6.7B (DeepSeek) & 1 & 59.95 \\\\\n\\midrule\nMajority (pass) & --- & --- & 51.75 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nAll three formulations achieve comparable accuracy on Qwen3-4B: \\cls{} 88.43\\% ($\\pm$0.78), \\cwm{} 87.19\\% ($\\pm$0.37), \\traj{} 86.30\\% ($\\pm$0.97). DeepSeek-Coder-6.7B shows: \\cls{} 86.85\\%, \\cwm{} 86.83\\%, \\traj{} 84.16\\%. The \\cls{}--\\cwm{} gap (0.02--1.24\\pp{}) is within seed noise in both families. However, the \\cls{}--\\traj{} gap is model-dependent: $<$1\\pp{} on Qwen3 but 2.69\\pp{} on DeepSeek-Coder, exceeding the $\\pm$2\\pp{} equivalence margin (\\S\\ref{sec:equivalence}). \\cls{} and \\cwm{} are robustly equivalent; \\traj{} parity is model-contingent. Zero-shot baselines (Tables~\\ref{tab:main_results} and~\\ref{tab:repo_level}) establish that repo-level verification requires fine-tuning (0-shot$\\to$fine-tuned gains of 35--36\\pp{}) and that formulation choice matters only at repo level (\\cls{} outperforms \\cwm{} by 19--26\\pp{}).\n\n\n\\subsection{Scaling Behavior}\n\\label{sec:scaling}\n\nBeyond overall accuracy, we examine whether formulation ranking is stable across model sizes. Table~\\ref{tab:scaling} compares all three formulations at 4B and 8B using seeds 42 and 123 in full bfloat16 precision (excluding NF4 seeds to isolate the size effect).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Model-size scaling: accuracy (\\%) at 4B and 8B (Qwen3, seeds 42/123, full bfloat16 precision). \\cls{} and \\traj{} scale positively; \\cwm{} does not.}\n\\label{tab:scaling}\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Size} & \\textbf{s42} & \\textbf{s123} & \\textbf{Mean} & \\textbf{$\\Delta$ 4B$\\to$8B} \\\\\n\\midrule\n\\cls{} & 4B & 87.83 & 89.52 & \\textbf{88.68} & \\multirow{2}{*}{+1.27} \\\\\n\\cls{} & 8B & \\textbf{90.48} & 89.40 & \\textbf{89.94} & \\\\\n\\midrule\n\\cwm{} & 4B & 87.51 & 87.20 & \\underline{87.36} & \\multirow{2}{*}{$-$0.03} \\\\\n\\cwm{} & 8B & 87.67 & 86.98 & 87.33 & \\\\\n\\midrule\n\\traj{} & 4B & 85.66 & 85.47 & 85.57 & \\multirow{2}{*}{+2.13} \\\\\n\\traj{} & 8B & 87.60 & 87.79 & \\underline{87.70} & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\cls{} and \\traj{} both scale positively from 4B to 8B (+1.27\\pp{} and +2.13\\pp{} respectively), while \\cwm{} remains flat ($-$0.03\\pp{}). At 8B, the ranking is \\cls{} (89.94) $>$ \\traj{} (87.70) $>$ \\cwm{} (87.33). The \\cls{}--\\cwm{} gap widens from 1.32\\pp{} at 4B to 2.62\\pp{} at 8B (Figure~\\ref{fig:scaling_gap}); clustered bootstrap on the 3-seed superset (42, 123, 456 for \\cls{}/\\cwm{}) yields $p = 0.0066$ (95\\% CI $[1.80, 2.71]$), which confirms the widening is not a sampling artifact.\n\n\\cwm{} flat scaling ($-$0.03\\pp{}) may reflect suboptimal hyperparameter transfer at 8B rather than a fundamental limitation; we do not claim generation \\emph{cannot} benefit from scale. At function level, outputs are short (integers, booleans) and format compliance is near-perfect; at repo level, output length grows to ${\\sim}$477 tokens on average, and the same generation bottleneck manifests as format collapse (51--74\\% unparseable; \\S\\ref{sec:repo}). \\traj{} also shows no scaling benefit at repo level (72.92\\% at both 4B and 8B); only \\cls{} scales positively across both complexity levels.\n\n\n\\subsection{Per-Test vs.\\ Trajectory-Level Equivalence}\n\\label{sec:equivalence}\n\nWe compare \\cls{} (aggregated via all-pass rule) against \\traj{} on 523 variant-level instances across five seeds.\\footnote{Seeds 789 and 0 use NF4 quantized inference; the remaining three use bfloat16. Restricting to bfloat16 seeds only (3 seeds) yields $p{=}0.128$: consistent in direction but underpowered due to reduced seed coverage.} The pooled gap is $-$0.45\\pp{} (95\\% CI [$-$1.71, +0.84]); the TOST equivalence test confirms statistical equivalence at $p = 0.007$ ($\\pm$2\\pp{} margin, Holm-Bonferroni corrected). Our $\\pm$2\\pp{} threshold follows the SESOI framework~\\cite{lakens2017}, set independently of the observed gap and grounded in deployment relevance: at function-level accuracy (85--88\\%), a 2\\pp{} difference corresponds to ${\\sim}$38 per-test predictions across 1,890 tests (${\\sim}$2--3 problems out of 114)---comparable to between-seed variation (0.37--0.97\\pp{} std, Table~\\ref{tab:main_results}) and checkpoint selection noise ($<$1\\pp{}, \\S\\ref{sec:threats}). A difference within this range is indistinguishable from training noise for pipeline selection decisions. Equivalence holds at margins as tight as $\\pm$1.52\\pp{} (Table~\\ref{tab:tost_sensitivity}), well below the pre-specified threshold. Within-problem predictions are correlated (intraclass correlation ICC $= 0.191$, $p < 0.0001$, design effect (DEFF) $= 3.97$); all statistical tests use clustered bootstrap accordingly. On DeepSeek-Coder, the observed \\cls{}--\\cwm{} gap of 0.02\\pp{} is consistent with equivalence, but with only 2 seeds the comparison is underpowered. The DeepSeek \\cls{}--\\traj{} gap (2.69\\pp{}) exceeds the $\\pm$2\\pp{} margin; \\traj{} parity is model-dependent rather than universal, while the \\cls{}--\\cwm{} equivalence is robust across both families. Per-test classification provides diagnostic information (which specific tests fail) at no cost to variant-level accuracy. This parallels process supervision~\\cite{lightman2023letsverify}: step-level verification enables error localization without accuracy loss.\n\nOracle analysis on SWE-bench Verified (500 instances) shows that per-test advantage concentrates at $T \\geq 2$ fail-to-pass tests (31.3\\% of instances, contributing 55.3\\% of the total oracle advantage; Appendix~\\ref{app:oracle}).\n\n\n\\subsection{Repo-Level: Complexity-Dependent Divergence}\n\\label{sec:repo}\n\nTable~\\ref{tab:repo_level} compares formulations at repository-level complexity. Variant-level comparisons rely on limited seed coverage; the per-test interaction effect is statistically confirmed (see below). Checkpoints are val-selected where validation loss is computable (\\S\\ref{sec:setup}); the test set has zero problem overlap with validation.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Repo-level cross-formulation comparison on SWE-bench Verified test set. Qwen3-8B \\cls{}/\\traj{}: mean $\\pm$ std over 3 seeds; DeepSeek \\cls{}: 2 seeds\\textsuperscript{$\\ddagger$}; DeepSeek \\traj{}: 3 seeds; Qwen3-4B: seed 42. \\cwm{} multi-seed runs in progress.}\n\\label{tab:repo_level}\n\\resizebox{\\columnwidth}{!}{%\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & \\textbf{\\cls{} (\\%)} & \\textbf{\\cls{} Var.\\ (\\%)} & \\textbf{\\cwm{} (\\%)} & \\textbf{\\traj{} Var.\\ (\\%)\\textsuperscript{$\\diamond$}} \\\\\n\\midrule\nQwen3-4B & 83.63 & 64.58 & 58.04 & 72.92 \\\\\nQwen3-8B & \\textbf{84.83 $\\pm$ 0.67} & 72.92 / 81.25\\textsuperscript{$\\dagger$} & \\tbd{} & 72.91 $\\pm$ 3.61 \\\\\nDeepSeek-6.7B & 84.38 $\\pm$ 2.50\\textsuperscript{$\\ddagger$} & 81.25\\textsuperscript{$\\dagger$} & \\tbd{} & 77.08 $\\pm$ 3.61 \\\\\n\\midrule\n0-shot (Qwen3-8B) & 49.90 & --- & --- & --- \\\\\n0-shot (DeepSeek) & 48.54 & --- & --- & --- \\\\\nMajority & 72.96 & 54.17 & 72.96 & 54.17 \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{2pt}\n{\\footnotesize \\textsuperscript{$\\dagger$}Individual-seed variant accuracy; multi-seed aggregate pending. \\textsuperscript{$\\ddagger$}One seed excluded: truncate preprocessing$\\to$NaN val loss, decision collapse (Table~\\ref{tab:taxonomy}); mean over two matched seeds. \\textsuperscript{$\\diamond$}Var.\\ columns: variant-level accuracy ($n{=}48$); \\cls{} aggregated via all-pass rule; \\traj{} by design. Per-test: $n{=}9{,}784$. \\cwm{} unparseable: 54\\% (4B); default to pass; parseable-only 38--43\\%, below majority. Eval seq\\_length differs across models (Appendix~\\ref{app:threats}). \\cwm{} uses epoch-3 checkpoint (val loss undefined); see text for checkpoint sensitivity analysis.}\n\\end{table}\n\nZero-shot prompting collapses to an always-predict-unresolved baseline (variant accuracy 45.83\\%, below majority 54.17\\%; Appendix~\\ref{app:few_shot}).\n\n\\paragraph{Formulation divergence (single-seed).} Under our 4--8B LoRA protocol, \\cls{} and \\cwm{} diverge on Qwen3: the gap is 25.59\\pp{} at 4B (\\cls{} 83.63\\% vs.\\ \\cwm{} 58.04\\%, seed 42; Figure~\\ref{fig:scaling_gap}) and 19.31\\pp{} at 8B (84.48\\% vs.\\ 65.17\\%). \\cwm{} falls below majority baseline at both scales. These gaps suggest complexity-dependent formulation effectiveness, though single-seed design and multiple confounds (\\S\\ref{sec:threats}) preclude definitive causal attribution.\n\n\\paragraph{Cross-model consistency.} DeepSeek-Coder shows the same direction (\\cls{} $>$ \\cwm{}) under single-seed constraints. DeepSeek \\cls{} degradation ranges from ${\\sim}$4\\pp{} (s42, drop preprocessing) to ${\\sim}$12\\pp{} (s123, truncate preprocessing), reflecting preprocessing and checkpoint selection sensitivity (Table~\\ref{tab:taxonomy}). The \\cls{}--\\cwm{} gap magnitude also varies across families (20\\pp{} for Qwen3 vs.\\ 23--28\\pp{} for DeepSeek), primarily reflecting checkpoint selection: DeepSeek \\cwm{}'s val-selected checkpoint (56.70\\%) underperforms its epoch-3 checkpoint (61.49\\%), widening the apparent gap. Under matched checkpoint selection (epoch~3 for both), the cross-model gap difference narrows to ${\\sim}$2\\pp{} (Qwen3: 20.47\\pp{} vs.\\ DeepSeek: 22.89\\pp{}). The gap is formulation-driven rather than model-specific. Eval seq\\_length differs between models (Appendix~\\ref{app:threats}).\n\n\\paragraph{Failure mode taxonomy.} Variant-level analysis ($n{=}48$, Appendix Table~\\ref{tab:variant_level}) reveals three failure modes (Table~\\ref{tab:taxonomy}): format collapse (\\cwm{}, 51--74\\% unparseable), decision collapse (\\cls{} under truncate preprocessing, fail recall ${\\sim}$14\\%), and aggregation penalty (\\cls{} under drop preprocessing, fail recall 38--57\\%). Decision collapse is configuration-dependent, not model-inherent. \\traj{} avoids aggregation penalty by predicting variant outcomes directly (72.91--77.08\\%). Downsampling \\cls{} training data to match \\traj{}'s data volume yields 80.74\\%, still 7.82\\pp{} above \\traj{}; this controls data volume but not label granularity (per-test vs.\\ variant-level), and remains a single-seed comparison (Appendix~\\ref{app:downsample}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Repo-level failure mode taxonomy. Variant-level majority baseline: 54.17\\%.}\n\\label{tab:taxonomy}\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Failure Mode} & \\textbf{Representative} & \\textbf{Fail Recall} & \\textbf{Variant Acc} \\\\\n\\midrule\nFormat collapse & \\cwm{} (all) & N/A & 48--52\\% \\\\\nDecision collapse & \\cls{} (DeepSeek, s123) & ${\\sim}$14\\% & 56\\% \\\\\nAggr.\\ penalty & \\cls{} (Qwen3-8B) & 51--57\\% & 73--81\\% \\\\\nAggr.\\ penalty & \\cls{} (DeepSeek, s42) & 38--51\\% & 79--81\\% \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Default assignment artifact.} The apparent \\cwm{} accuracy increase from 4B to 8B is an artifact of rising unparseable rate (53.7\\%$\\to$73.8\\%), which inflates accuracy via majority-class default while parseable-only accuracy decreases (42.88\\%$\\to$38.52\\%; Appendix~\\ref{app:parseable_bias}).\n\n\\paragraph{Complexity as moderator.} The \\cls{}--\\cwm{} gap widens from 1--3\\pp{} (function) to 19--26\\pp{} (repo) under our protocol; a matched-context ablation confirms input disparity explains $<$3\\% of this gap (Appendix~\\ref{app:ablations}).\n\n\\paragraph{Formulation$\\times$complexity interaction.} A mixed-effects linear probability model with problem-level random intercepts ($n{=}56{,}480$ observations, 139 problem clusters, DeepSeek-Coder) confirms the interaction: the \\cwm{} effect at function level is negligible ($\\hat{\\beta}{=}-0.002$, $p{=}0.805$), but the formulation$\\times$complexity interaction is highly significant ($z{=}-23.7$, $p{<}0.001$). \\cwm{} and \\cls{} are statistically indistinguishable at function level ($\\Delta{=}-0.2$\\pp{}) but diverge by 22\\pp{} at repo level, confirming the divergence is not an artifact of aggregation. The cross-complexity analysis uses DeepSeek-Coder, the only family with both function- and repo-level \\cwm{} evaluations under matched conditions. Across both model families at repo level, the \\cwm{} deficit is $-$22\\pp{} ($z{=}-64.4$, $p{<}0.001$); the model family effect is significant but small (+1.1\\pp{} for Qwen3, $p{=}0.002$), and the formulation$\\times$model interaction is likewise small (+1.6\\pp{}, $p{=}0.006$). Formulation explains $>$95\\% of the predictable variance; model identity modulates gap magnitude without changing direction (Appendix~\\ref{app:interaction}).\n\nAdditional repo-level limitations appear in Appendix~\\ref{app:limitations}.\n\n\n\\subsection{Analysis}\n\\label{sec:analysis}\n\n\\paragraph{Aggregation penalty.} Under the all-pass rule, a single false negative flips the variant verdict. The penalty ranges from 1.36\\pp{} (DeepSeek s42) to 19\\pp{} (Qwen3-4B), depending on fail recall and test count (Appendix Table~\\ref{tab:variant_level}). Val-based checkpoint selection biases toward per-test accuracy at the expense of fail recall, which amplifies the penalty. \\traj{} avoids this by predicting variant outcomes directly (72.91--77.08\\%). The penalty is predictable from test count: function-level variants ($\\bar{T} \\approx 2.3$) incur negligible penalty, while repo-level variants ($\\bar{T} \\gg 10$) incur substantial penalty, both the \\emph{advantage} and \\emph{cost} of per-test granularity concentrate at high $T$ (Appendix~\\ref{app:extended_analysis}(a)).\n\n\\paragraph{Why does generation degrade at repo level?} Output space complexity increases nonlinearly: function-level outputs are short strings (integers, booleans); repo-level outputs are unconstrained execution traces (mean ${\\sim}$477 tokens) where errors compound multiplicatively, and cause format collapse (53--74\\% unparseable). Even among parseable outputs, accuracy (38--43\\%) is below majority baseline, which indicates a semantic gap beyond format compliance (Appendix~\\ref{app:qualitative}).\n\n\\cls{} achieves 217$\\times$ higher throughput than \\cwm{} (1 output token vs.\\ avg 477), consistent across both model families.\n\n\\paragraph{Error complementarity.} At function level, \\cls{} and \\cwm{} exhibit partial complementarity: both are FP-dominant (over-predict failure), but at different rates (\\cls{} 56.5\\%, \\cwm{} 70.3\\%; Appendix~\\ref{app:extended_analysis}(a)), so \\cwm{} over-predicts failure on instances \\cls{} correctly classifies. An oracle combination achieves 90.63\\% (+2.80\\pp{} over the best single formulation; single-seed estimate). At repo level, oracle routing across configurations reaches 95.83\\% variant accuracy (+14.58\\pp{} over the best single configuration, $n{=}48$), the strongest evidence that the formulation design space contains complementary solutions worth exploring. A re-repair pilot found no benefit from per-test diagnostics ($n{=}44$, $p{=}0.42$; Appendix~\\ref{app:extended_analysis}(j)). Extended analysis appears in Appendix~\\ref{app:extended_analysis}.\n\n\\subsection{Threats to Validity}\n\\label{sec:threats}\n\nWe identify five potential confounds and assess each in Appendix~\\ref{app:threats}: checkpoint selection ($<$1\\pp{} variation in ablation; NaN validation loss forces final-epoch default in all \\cwm{} runs and DeepSeek \\cls{} s123), evaluation sequence length (${\\sim}$1.5\\pp{}), preprocessing (${\\sim}$8\\pp{} cross-configuration variance), \\traj{} training regime (downsample confirms formulation advantage), and \\cwm{} scale/pretraining (primary limitation; all repo-level \\cwm{} conclusions conditional on the ${\\leq}$8B LoRA regime). The 19--26\\pp{} gap exceeds any single assessed confound, but correlated confounds and limited seeds mean definitive causal attribution requires multi-seed replication. Holm-Bonferroni correction confirms the two core claims survive (adjusted $p{=}0.012$ and $p{=}0.021$; Table~\\ref{tab:holm}).\n",
      "numLines": 184,
      "startLine": 1,
      "totalLines": 184
    }
  },
  "sourceToolAssistantUUID": "976d33ca-7007-458d-a7aa-e6e6d58cfb5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-21T15:15:06.447Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Av4PdgKj3ayrHpgtbZNJm7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "634f9a5c-c9f4-4a99-879d-20b041668733",
  "isSidechain": false,
  "requestId": "req_011CbFw5LBrLTbgAZViyq7fK",
  "type": "assistant",
  "uuid": "dfaaf263-d95b-475c-8c06-83c27f0556df",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011DoB1jz7aNEmrxedrFHCwQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13336,
      "cache_read_input_tokens": 11447,
      "output_tokens": 337,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13336,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 337,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 13336,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13336
          },
          "type": "message"
        }
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

_source line 18_

```json
{
  "type": "last-prompt",
  "leafUuid": "2905a3ad-5728-44a2-a0a6-9f0a9259aad3",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Runtime record

_source line 19_

```json
{
  "type": "ai-title",
  "aiTitle": "Scan appendix.tex for residual issues",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Assistant

_source line 20 · 2026-05-21T15:17:18.574Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all four files. Let me systematically check each item:

## 1. Placeholder/Tentative Wording

Scanning appendix.tex for: "preliminary", "in progress", "TBD", "TODO", "placeholder", "to be", "forthcoming", \tbd{}

Line 120 in experiments.tex: `\tbd{}` appears in Table 2 for Qwen3-8B CWM and DeepSeek CWM columns


Line 121 also has `\tbd{}`. Let me verify this is experiments.tex and not appendix.tex. Checking appendix.tex carefully now... I'm not finding any of those placeholder markers there. But I do see "in progress" on line 111 of experiments.tex in the table caption, though that's a different file. Let me scan appendix.tex more thoroughly for any tentative language.

I'm finding some concerning wording in appendix.tex: line 67 has a footnote mentioning "unverified checkpoint" and "may differ," which sounds tentative. More importantly, I'm noticing a numerical discrepancy—line 304 reports parseable predictions at 42–53%, but line 322 reports them at 38–43%. These should match if they're describing the same thing.

Looking deeper, I see line 174 in experiments.tex says 38–43%, which aligns with line 322, while line 160 shows 42.88%→38.52%. The paragraph (c) figure of 42–53% might be referencing something different—possibly repo-level results with specific seeds (42 and 123) versus function-level analysis, but I need to verify this more carefully to understand why the ranges diverge. I need to systematically check each number against the main text to identify any inconsistencies. Let me start by verifying the 19-26pp gap across different sections, then move through the z-statistic and oracle accuracy figures to see where discrepancies might exist. The 217× throughput metric and ~370 GPU-hours are consistent across all sections. The TOST p-value of 0.007 also checks out consistently in the main text, conclusion, and appendix. Now I'm verifying the parseable predictions range across documents.

The main text shows 42.88%→38.52% with a range of 38–43%, but the appendix has conflicting ranges: paragraph (c) mentions 42–53% while paragraph (g) aligns with the main text at 38–43%. Looking more closely at paragraph (c), the 42–53% refers specifically to the model's own parseable predictions performance, which is a different metric than the overall accuracy range, so these aren't actually inconsistent. I'm realizing these are measuring different things—the main text compares model sizes (4B to 8B), while the appendix is looking at sequence length changes (4096 to 8192 tokens). That's worth noting as a potential source of confusion in the paper. The 54% rounding in the table caption is reasonable given the 53.7% figure in the main text. But I'm noticing a real inconsistency with the parseable prediction accuracy—paragraph (c) cites 42–53% while paragraph (g) and the main text both reference 38–43%, which are substantially different ranges. I need to figure out if the 42–53% might be referring to a different evaluation condition like relaxed matching. The 42-53% range is puzzling since I haven't seen 53% anywhere in the data—it might span multiple model configurations, but I should flag this as an inconsistency to resolve. The majority-voting footnote on line 67 notes the values came from an unverified checkpoint, which needs to be either confirmed before submission or the numbers updated accordingly. I also notice the experiments.tex file has "\cwm{} multi-seed runs in progress" in a table caption, though I should verify if there are any \tbd{} markers in Table 2 as well.

Looking at the checkpoint and footnote issues more broadly, I'm seeing some numerical discrepancies too—the appendix mentions aggregation penalty ranges of 1pp to 19pp while the main text says 1.36pp to 19pp, which are close enough, but the 90.63% accuracy figure in the appendix includes specific seed and comparison details that should be consistent across documents.

Now I'm noticing some significant redundancy across sections: the Extended Analysis paragraph on rank 32 ablations and majority voting repeats what's already covered in the appendix ablations section, and the threats analysis appears in both the appendix and main text with nearly identical wording at the end, which suggests I should consolidate or clarify which version is authoritative.

I'm also spotting some data quality issues—the CWM 4B table caption uses "unavailable" as a placeholder, one footnote indicates incomplete evaluation coverage at ~75%, and there's a statistical result on the re-repair pilot that seems to cut off mid-comparison to the main text.

Now I'm cross-checking the specific numbers the user flagged, and most are holding up consistently across sections. But I'm finding a discrepancy in the parseable-only accuracy figures—paragraph (c) reports "42-53%" while both paragraph (g) and the main text say "38-43%"—and a minor rounding inconsistency with the unparseable rate at 73.8% versus 74%.

There's also an "unverified checkpoint" reference in a footnote that I should investigate further. Looking at line 322, the "38-43%" range seems to approximate the 4B→8B model performance of 42.88%→38.52%, which is reasonable, but paragraph (c)'s "42-53%" appears to reference something different—possibly the relaxed matching context—and the text doesn't clearly distinguish between these different scenarios. I'm checking the actual numbers from the 4B model: the standard gap between CLS and CWM is about 25.59pp, which rounds to 26pp, but under relaxed matching it should only widen to around 26.65pp (roughly 27pp), not 28pp as stated. This discrepancy suggests the paragraph might be referencing seed 123 results or a different CLS value than what I'm seeing in the main text. Looking at the calculation more carefully, averaging across seeds gives around 25pp rather than 26pp, so that "26pp to 28pp" claim needs verification against the actual numbers. Let me scan through the appendix for other tentative language and incomplete data—I'm seeing phrases like "may differ slightly," "unavailable," dashes in table cells for missing values, and partial evaluation notes. I also notice "tentative" appears explicitly in the repo-level comparison section around line 453.

Now I'm finding the real issue: line 67 admits these majority-voting values came from an unverified checkpoint and may differ from the final val-best results, which is a clear pre-submission problem. Let me cross-check some of the percentage claims—the parseable predictions percentages match between the appendix and experiments file, but there's a mismatch in paragraph (c) where "42–53%" doesn't align with what I'm seeing in the main text.

Looking more carefully at the context, paragraph (c) seems to be discussing CWM parseable predictions across different seeds for the 4B model, so if seed 42 gives 42.88% and seed 123 gives around 53%, that range would actually make sense. The 38-43% range likely spans both model scales at the repository level. I'm getting bogged down in these details, so let me just note the discrepancy and move forward. Checking the appendix against the main text on GPU hours: the appendix clearly states ~370 GPU-hours across 223 runs with various configurations, though I haven't located where the main text explicitly mentions this figure yet.

I should flag that Table 2 in experiments.tex has a \tbd{} marker for CWM multi-seed results, which could affect any appendix content referencing those results. Before writing the report, let me scan the appendix for tentative language and data gaps—I'm finding several instances of speculative phrasing like "may differ slightly" and "unavailable" data, with at least one explicit "tentative" marker around line 453.

Most of these are acceptable scientific hedging, but the footnote on line 67 about an "unverified checkpoint" is problematic for submission since it suggests the numbers aren't finalized. The CLS-TRAJ comparison being tentative is legitimate, as is the "may diminish" qualifier. The good news is there's no \tbd{} in the appendix itself—only in experiments.tex—so that's contained.

Now I'm checking for redundancy issues, starting with paragraph (g). I've reviewed the redundancy issues across the appendix sections and identified where synthesis paragraphs overlap with detailed tables and ablation studies. The threats section properly expands on the main text summary, but the failed interventions paragraph and mutation scaling patterns could be trimmed since their underlying data already exists elsewhere. Now I'm ready to draft the report.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2905a3ad-5728-44a2-a0a6-9f0a9259aad3",
  "isSidechain": false,
  "requestId": "req_011CbFw5kdmqAtF7XwLun8Bh",
  "type": "assistant",
  "uuid": "d1953c2a-6068-46e2-ad3c-27e28645f0f8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Bv1zzq5FuGyVRGFzDbWLEL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26429,
      "cache_read_input_tokens": 24783,
      "output_tokens": 6783,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26429,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6783,
          "cache_read_input_tokens": 24783,
          "cache_creation_input_tokens": 26429,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26429
          },
          "type": "message"
        }
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

_source line 21 · 2026-05-21T15:17:18.576Z_

Now I have all files. Let me also search the appendix for specific placeholder patterns to be thorough.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d1953c2a-6068-46e2-ad3c-27e28645f0f8",
  "isSidechain": false,
  "requestId": "req_011CbFw5kdmqAtF7XwLun8Bh",
  "type": "assistant",
  "uuid": "9a101de4-231e-426e-b307-236b80be01b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Bv1zzq5FuGyVRGFzDbWLEL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26429,
      "cache_read_input_tokens": 24783,
      "output_tokens": 6783,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26429,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6783,
          "cache_read_input_tokens": 24783,
          "cache_creation_input_tokens": 26429,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26429
          },
          "type": "message"
        }
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

_source line 22 · 2026-05-21T15:17:20.859Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01ArB4p1jR9ew55AH28YKcyP`</summary>

```json
{
  "pattern": "(preliminary|in progress|TBD|TODO|placeholder|to be completed|forthcoming|\\\\tbd|tentative|unverified|unavailable|pending|may differ)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9a101de4-231e-426e-b307-236b80be01b2",
  "isSidechain": false,
  "requestId": "req_011CbFw5kdmqAtF7XwLun8Bh",
  "type": "assistant",
  "uuid": "99a2a77a-3e63-42fb-a1a5-d5b09b459506",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Bv1zzq5FuGyVRGFzDbWLEL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26429,
      "cache_read_input_tokens": 24783,
      "output_tokens": 6783,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26429,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6783,
          "cache_read_input_tokens": 24783,
          "cache_creation_input_tokens": 26429,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26429
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-21T15:17:21.467Z_

<details><summary>↩ Tool result · `toolu_01QyfwS4yMarRNDJj43vawBd`</summary>

```text
docs/paper/experiments.tex:120:Qwen3-8B & \textbf{84.83 $\pm$ 0.67} & 72.92 / 81.25\textsuperscript{$\dagger$} & \tbd{} & 72.91 $\pm$ 3.61 \\
docs/paper/experiments.tex:121:DeepSeek-6.7B & 84.38 $\pm$ 2.50\textsuperscript{$\ddagger$} & 81.25\textsuperscript{$\dagger$} & \tbd{} & 77.08 $\pm$ 3.61 \\
docs/paper/main.tex:31:\newcommand{\tbd}{\textsc{tbd}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b09b77d5-8b1d-4dea-9ff9-1bac16b4aac6",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "a041d13b-d293-4791-b748-ee36235abd77",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/experiments.tex:120:Qwen3-8B & \\textbf{84.83 $\\pm$ 0.67} & 72.92 / 81.25\\textsuperscript{$\\dagger$} & \\tbd{} & 72.91 $\\pm$ 3.61 \\\\\ndocs/paper/experiments.tex:121:DeepSeek-6.7B & 84.38 $\\pm$ 2.50\\textsuperscript{$\\ddagger$} & 81.25\\textsuperscript{$\\dagger$} & \\tbd{} & 77.08 $\\pm$ 3.61 \\\\\ndocs/paper/main.tex:31:\\newcommand{\\tbd}{\\textsc{tbd}}",
    "numLines": 3
  },
  "sourceToolAssistantUUID": "b09b77d5-8b1d-4dea-9ff9-1bac16b4aac6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-21T15:17:20.896Z_

<details><summary>↩ Tool result · `toolu_01ArB4p1jR9ew55AH28YKcyP`</summary>

```text
67:Majority voting ($K{=}3$) decreases accuracy from 87.51\% to 86.83\% ($-$0.68\pp{}): errors are systematic rather than stochastic, so sampling-based ensembles do not help.\footnote{These majority-voting values were computed from an unverified checkpoint and may differ slightly from the val-best checkpoint results.}
110:\caption{Per-mutation test accuracy (\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \cls{} 8B reports two seeds; $\Delta$ is mean 4B$\to$8B gain for \cls{}. \cwm{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\%, parseable acc 23.5\%).}
334:[Omitted long matching line]
447:[Omitted long matching line]
463:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "99a2a77a-3e63-42fb-a1a5-d5b09b459506",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "3915435f-281b-459e-aa2f-6ff64415bb27",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "67:Majority voting ($K{=}3$) decreases accuracy from 87.51\\% to 86.83\\% ($-$0.68\\pp{}): errors are systematic rather than stochastic, so sampling-based ensembles do not help.\\footnote{These majority-voting values were computed from an unverified checkpoint and may differ slightly from the val-best checkpoint results.}\n110:\\caption{Per-mutation test accuracy (\\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \\cls{} 8B reports two seeds; $\\Delta$ is mean 4B$\\to$8B gain for \\cls{}. \\cwm{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\\%, parseable acc 23.5\\%).}\n334:[Omitted long matching line]\n447:[Omitted long matching line]\n463:[Omitted long matching line]",
    "numLines": 5
  },
  "sourceToolAssistantUUID": "99a2a77a-3e63-42fb-a1a5-d5b09b459506",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-21T15:17:21.455Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01QyfwS4yMarRNDJj43vawBd`</summary>

```json
{
  "pattern": "\\\\tbd",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3915435f-281b-459e-aa2f-6ff64415bb27",
  "isSidechain": false,
  "requestId": "req_011CbFw5kdmqAtF7XwLun8Bh",
  "type": "assistant",
  "uuid": "b09b77d5-8b1d-4dea-9ff9-1bac16b4aac6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Bv1zzq5FuGyVRGFzDbWLEL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 26429,
      "cache_read_input_tokens": 24783,
      "output_tokens": 6783,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26429,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6783,
          "cache_read_input_tokens": 24783,
          "cache_creation_input_tokens": 26429,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26429
          },
          "type": "message"
        }
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

_source line 26_

```json
{
  "type": "last-prompt",
  "leafUuid": "a041d13b-d293-4791-b748-ee36235abd77",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Runtime record

_source line 27_

```json
{
  "type": "ai-title",
  "aiTitle": "Scan appendix.tex for residual issues",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Assistant

_source line 28 · 2026-05-21T15:17:26.153Z_

<details><summary>Logged reasoning block</summary>

```text
Good. Now I have a clear picture. Let me also check the parseable-only accuracy inconsistency more carefully. In paragraph (c) vs (g):
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a041d13b-d293-4791-b748-ee36235abd77",
  "isSidechain": false,
  "requestId": "req_011CbFwFhTojbPcdQ1Lcbbka",
  "type": "assistant",
  "uuid": "9d2cb5dd-1521-4b86-abb7-18071ba0627f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BdpTYCn5zeVayoiPtEKLpZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7256,
      "cache_read_input_tokens": 51212,
      "output_tokens": 375,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 375,
          "cache_read_input_tokens": 51212,
          "cache_creation_input_tokens": 7256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7256
          },
          "type": "message"
        }
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

_source line 29 · 2026-05-21T15:17:27.106Z_

Now let me check one more specific inconsistency — the parseable-only accuracy range discrepancy between paragraphs (c) and (g).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9d2cb5dd-1521-4b86-abb7-18071ba0627f",
  "isSidechain": false,
  "requestId": "req_011CbFwFhTojbPcdQ1Lcbbka",
  "type": "assistant",
  "uuid": "435d4e1b-2ff9-44f5-ad7b-f4556be31f56",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BdpTYCn5zeVayoiPtEKLpZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7256,
      "cache_read_input_tokens": 51212,
      "output_tokens": 375,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 375,
          "cache_read_input_tokens": 51212,
          "cache_creation_input_tokens": 7256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7256
          },
          "type": "message"
        }
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

_source line 30 · 2026-05-21T15:17:28.552Z_

<details open><summary>🔧 Tool call — Grep · `toolu_011KEixc9UWeCqvrxCs2rtKX`</summary>

```json
{
  "pattern": "parseable.*predict|parseable.*acc|38.*43|42.*53",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "435d4e1b-2ff9-44f5-ad7b-f4556be31f56",
  "isSidechain": false,
  "requestId": "req_011CbFwFhTojbPcdQ1Lcbbka",
  "type": "assistant",
  "uuid": "baa2fe27-f9ec-4c67-9e33-7c599bfd0395",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BdpTYCn5zeVayoiPtEKLpZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7256,
      "cache_read_input_tokens": 51212,
      "output_tokens": 375,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 375,
          "cache_read_input_tokens": 51212,
          "cache_creation_input_tokens": 7256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7256
          },
          "type": "message"
        }
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

_source line 31 · 2026-05-21T15:17:29.570Z_

<details><summary>↩ Tool result · `toolu_01G9cRsJttYsLVmcaajovz4p`</summary>

```text
304:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "68621cb1-776c-460a-921d-ef4c6ec125d9",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "1b2e0b0e-d630-4385-9f8b-7b43585be209",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "304:[Omitted long matching line]",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "68621cb1-776c-460a-921d-ef4c6ec125d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-21T15:17:28.612Z_

<details><summary>↩ Tool result · `toolu_011KEixc9UWeCqvrxCs2rtKX`</summary>

```text
docs/paper/experiments.tex:130:[Omitted long matching line]
docs/paper/experiments.tex:139:[Omitted long matching line]
docs/paper/experiments.tex:160:\paragraph{Default assignment artifact.} The apparent \cwm{} accuracy increase from 4B to 8B is an artifact of rising unparseable rate (53.7\%$\to$73.8\%), which inflates accuracy via majority-class default while parseable-only accuracy decreases (42.88\%$\to$38.52\%; Appendix~\ref{app:parseable_bias}).
docs/paper/experiments.tex:174:[Omitted long matching line]
docs/paper/main.log:1456: 42253 multiletter control sequences out of 15000+600000
docs/paper/method.tex:13:[Omitted long matching line]
docs/paper/method.tex:22:[Omitted long matching line]
docs/paper/main.fdb_latexmk:11:  "../../artifacts/figures/paper/fig1_reformulation.pdf" 1779364892.36129 23422 992bd1d784c18b1e7535f67dba4b18ff ""
docs/paper/main.fdb_latexmk:38:  "/usr/share/texlive/texmf-dist/fonts/tfm/public/amsfonts/symbols/msbm7.tfm" 1246382020 940 228d6584342e91276bf566bcf9716b83 ""
docs/paper/main.fdb_latexmk:95:  "/usr/share/texlive/texmf-dist/tex/generic/pdftexcmds/pdftexcmds.sty" 1593379760 20089 80423eac55aa175305d35b49e04fe23b ""
docs/paper/main.fdb_latexmk:148:  "/usr/share/texlive/texmf-dist/tex/latex/xcolor/xcolor.sty" 1727642399 55384 b454dec21c2d9f45ec0b793f0995b992 ""
docs/paper/main.fdb_latexmk:153:  "abstract.tex" 1779346377.38261 1265 ec8be2394c38e598843ea7f4a1a1b868 ""
docs/paper/appendix.tex:50:\caption{LoRA rank ablation for \cwm{} 4B (seed 42, 3 epochs, lr $= 2{\times}10^{-4}$). Rank-16 seed variance: 0.53\pp{} (seeds 42 vs.\ 456).}
docs/paper/appendix.tex:105:Table~\ref{tab:mutation_breakdown} compares per-mutation accuracy at repo level. \cls{} produces 0\% unparseable outputs; all values are direct classification accuracy. \cwm{} overall accuracy includes default-pass assignment for unparseable outputs (see \S\ref{sec:repo}).
docs/paper/appendix.tex:110:\caption{Per-mutation test accuracy (\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \cls{} 8B reports two seeds; $\Delta$ is mean 4B$\to$8B gain for \cls{}. \cwm{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\%, parseable acc 23.5\%).}
docs/paper/appendix.tex:132:\caption{\cwm{} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\%) for gold at both scales.}
docs/paper/appendix.tex:150:[Omitted long matching line]
docs/paper/appendix.tex:286:[Omitted long matching line]
docs/paper/appendix.tex:304:[Omitted long matching line]
docs/paper/appendix.tex:322:\item \textbf{Relaxed matching (L0--L4):} Tolerating format deviations \emph{decreases} accuracy from 58.04\% to 56.98\% (seed 42; Appendix~\ref{app:extended_analysis}(c)), because unparseable predictions default to the majority class (pass, 72.96\%), which outperforms the model's own parseable predictions (38--43\%).
docs/paper/appendix.tex:323:\item \textbf{Model scaling (4B$\to$8B):} Parseable-only accuracy decreases (42.88\%$\to$38.52\%) while unparseable rate increases (53.7\%$\to$73.8\%); the apparent accuracy gain is entirely a default-assignment artifact (\S\ref{sec:repo}).
docs/paper/appendix.tex:332:[Omitted long matching line]
docs/paper/appendix.tex:439:[Omitted long matching line]
docs/paper/appendix.tex:449:[Omitted long matching line]
docs/paper/main.aux:1293:\@writefile{lot}{\contentsline {table}{\numberline {6}{\ignorespaces LoRA rank ablation for \textsc  {Cwm}{} 4B (seed 42, 3 epochs, lr $= 2{\times }10^{-4}$). Rank-16 seed variance: 0.53\,\text  {pp}{} (seeds 42 vs.\ 456).}}{13}{table.caption.54}\protected@file@percent }
docs/paper/main.aux:1294:\newlabel{tab:rank_ablation}{{6}{13}{LoRA rank ablation for \cwm {} 4B (seed 42, 3 epochs, lr $= 2{\times }10^{-4}$). Rank-16 seed variance: 0.53\pp {} (seeds 42 vs.\ 456)}{table.caption.54}{}}
docs/paper/main.aux:1378:\@writefile{lot}{\contentsline {table}{\numberline {8}{\ignorespaces Per-mutation test accuracy (\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \textsc  {Cls}{} 8B reports two seeds; $\Delta $ is mean 4B$\to $8B gain for \textsc  {Cls}{}. \textsc  {Cwm}{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\%, parseable acc 23.5\%).}}{14}{table.caption.60}\protected@file@percent }
docs/paper/main.aux:1379:\newlabel{tab:mutation_breakdown}{{8}{14}{Per-mutation test accuracy (\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \cls {} 8B reports two seeds; $\Delta $ is mean 4B$\to $8B gain for \cls {}. \cwm {} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\%, parseable acc 23.5\%)}{table.caption.60}{}}
docs/paper/main.aux:1382:\@writefile{lot}{\contentsline {table}{\numberline {9}{\ignorespaces \textsc  {Cwm}{} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\%) for gold at both scales.}}{14}{table.caption.61}\protected@file@percent }
docs/paper/main.aux:1383:\newlabel{tab:cwm_mutation_parse}{{9}{14}{\cwm {} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\%) for gold at both scales}{table.caption.61}{}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "baa2fe27-f9ec-4c67-9e33-7c599bfd0395",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "f9961ca3-65bf-469d-b108-7d98de7c2efd",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/experiments.tex:130:[Omitted long matching line]\ndocs/paper/experiments.tex:139:[Omitted long matching line]\ndocs/paper/experiments.tex:160:\\paragraph{Default assignment artifact.} The apparent \\cwm{} accuracy increase from 4B to 8B is an artifact of rising unparseable rate (53.7\\%$\\to$73.8\\%), which inflates accuracy via majority-class default while parseable-only accuracy decreases (42.88\\%$\\to$38.52\\%; Appendix~\\ref{app:parseable_bias}).\ndocs/paper/experiments.tex:174:[Omitted long matching line]\ndocs/paper/main.log:1456: 42253 multiletter control sequences out of 15000+600000\ndocs/paper/method.tex:13:[Omitted long matching line]\ndocs/paper/method.tex:22:[Omitted long matching line]\ndocs/paper/main.fdb_latexmk:11:  \"../../artifacts/figures/paper/fig1_reformulation.pdf\" 1779364892.36129 23422 992bd1d784c18b1e7535f67dba4b18ff \"\"\ndocs/paper/main.fdb_latexmk:38:  \"/usr/share/texlive/texmf-dist/fonts/tfm/public/amsfonts/symbols/msbm7.tfm\" 1246382020 940 228d6584342e91276bf566bcf9716b83 \"\"\ndocs/paper/main.fdb_latexmk:95:  \"/usr/share/texlive/texmf-dist/tex/generic/pdftexcmds/pdftexcmds.sty\" 1593379760 20089 80423eac55aa175305d35b49e04fe23b \"\"\ndocs/paper/main.fdb_latexmk:148:  \"/usr/share/texlive/texmf-dist/tex/latex/xcolor/xcolor.sty\" 1727642399 55384 b454dec21c2d9f45ec0b793f0995b992 \"\"\ndocs/paper/main.fdb_latexmk:153:  \"abstract.tex\" 1779346377.38261 1265 ec8be2394c38e598843ea7f4a1a1b868 \"\"\ndocs/paper/appendix.tex:50:\\caption{LoRA rank ablation for \\cwm{} 4B (seed 42, 3 epochs, lr $= 2{\\times}10^{-4}$). Rank-16 seed variance: 0.53\\pp{} (seeds 42 vs.\\ 456).}\ndocs/paper/appendix.tex:105:Table~\\ref{tab:mutation_breakdown} compares per-mutation accuracy at repo level. \\cls{} produces 0\\% unparseable outputs; all values are direct classification accuracy. \\cwm{} overall accuracy includes default-pass assignment for unparseable outputs (see \\S\\ref{sec:repo}).\ndocs/paper/appendix.tex:110:\\caption{Per-mutation test accuracy (\\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \\cls{} 8B reports two seeds; $\\Delta$ is mean 4B$\\to$8B gain for \\cls{}. \\cwm{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\\%, parseable acc 23.5\\%).}\ndocs/paper/appendix.tex:132:\\caption{\\cwm{} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\\%) for gold at both scales.}\ndocs/paper/appendix.tex:150:[Omitted long matching line]\ndocs/paper/appendix.tex:286:[Omitted long matching line]\ndocs/paper/appendix.tex:304:[Omitted long matching line]\ndocs/paper/appendix.tex:322:\\item \\textbf{Relaxed matching (L0--L4):} Tolerating format deviations \\emph{decreases} accuracy from 58.04\\% to 56.98\\% (seed 42; Appendix~\\ref{app:extended_analysis}(c)), because unparseable predictions default to the majority class (pass, 72.96\\%), which outperforms the model's own parseable predictions (38--43\\%).\ndocs/paper/appendix.tex:323:\\item \\textbf{Model scaling (4B$\\to$8B):} Parseable-only accuracy decreases (42.88\\%$\\to$38.52\\%) while unparseable rate increases (53.7\\%$\\to$73.8\\%); the apparent accuracy gain is entirely a default-assignment artifact (\\S\\ref{sec:repo}).\ndocs/paper/appendix.tex:332:[Omitted long matching line]\ndocs/paper/appendix.tex:439:[Omitted long matching line]\ndocs/paper/appendix.tex:449:[Omitted long matching line]\ndocs/paper/main.aux:1293:\\@writefile{lot}{\\contentsline {table}{\\numberline {6}{\\ignorespaces LoRA rank ablation for \\textsc  {Cwm}{} 4B (seed 42, 3 epochs, lr $= 2{\\times }10^{-4}$). Rank-16 seed variance: 0.53\\,\\text  {pp}{} (seeds 42 vs.\\ 456).}}{13}{table.caption.54}\\protected@file@percent }\ndocs/paper/main.aux:1294:\\newlabel{tab:rank_ablation}{{6}{13}{LoRA rank ablation for \\cwm {} 4B (seed 42, 3 epochs, lr $= 2{\\times }10^{-4}$). Rank-16 seed variance: 0.53\\pp {} (seeds 42 vs.\\ 456)}{table.caption.54}{}}\ndocs/paper/main.aux:1378:\\@writefile{lot}{\\contentsline {table}{\\numberline {8}{\\ignorespaces Per-mutation test accuracy (\\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \\textsc  {Cls}{} 8B reports two seeds; $\\Delta $ is mean 4B$\\to $8B gain for \\textsc  {Cls}{}. \\textsc  {Cwm}{} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\\%, parseable acc 23.5\\%).}}{14}{table.caption.60}\\protected@file@percent }\ndocs/paper/main.aux:1379:\\newlabel{tab:mutation_breakdown}{{8}{14}{Per-mutation test accuracy (\\%) at repo level (SWE-bench Verified, $n{=}9{,}784$). \\cls {} 8B reports two seeds; $\\Delta $ is mean 4B$\\to $8B gain for \\cls {}. \\cwm {} 4B per-mutation overall accuracy unavailable except gold (computed from parse rate 43.5\\%, parseable acc 23.5\\%)}{table.caption.60}{}}\ndocs/paper/main.aux:1382:\\@writefile{lot}{\\contentsline {table}{\\numberline {9}{\\ignorespaces \\textsc  {Cwm}{} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\\%) for gold at both scales.}}{14}{table.caption.61}\\protected@file@percent }\ndocs/paper/main.aux:1383:\\newlabel{tab:cwm_mutation_parse}{{9}{14}{\\cwm {} parse rates and parseable-only accuracy per mutation type (seed 42). Parse rate decreases uniformly from 4B to 8B; parseable-only accuracy is below random binary chance (50\\%) for gold at both scales}{table.caption.61}{}}",
    "numLines": 30
  },
  "sourceToolAssistantUUID": "baa2fe27-f9ec-4c67-9e33-7c599bfd0395",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-21T15:17:29.554Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01G9cRsJttYsLVmcaajovz4p`</summary>

```json
{
  "pattern": "26.*pp.*28.*pp|divergence widens",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f9961ca3-65bf-469d-b108-7d98de7c2efd",
  "isSidechain": false,
  "requestId": "req_011CbFwFhTojbPcdQ1Lcbbka",
  "type": "assistant",
  "uuid": "68621cb1-776c-460a-921d-ef4c6ec125d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BdpTYCn5zeVayoiPtEKLpZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7256,
      "cache_read_input_tokens": 51212,
      "output_tokens": 375,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7256,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 375,
          "cache_read_input_tokens": 51212,
          "cache_creation_input_tokens": 7256,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7256
          },
          "type": "message"
        }
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

_source line 34 · 2026-05-21T15:17:29.623Z_

```json
{
  "parentUuid": "1b2e0b0e-d630-4385-9f8b-7b43585be209",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "4300bbfb-6056-4b22-b2db-e3e077407690",
  "timestamp": "2026-05-21T15:17:29.623Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 35 · 2026-05-21T15:17:32.712Z_

<details><summary>Logged reasoning block</summary>

```text
OK, now I have everything I need. Let me also read the specific line to get the exact "divergence widens" wording:
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4300bbfb-6056-4b22-b2db-e3e077407690",
  "isSidechain": false,
  "requestId": "req_011CbFwGHyTVBwk4DJ9XrqFb",
  "type": "assistant",
  "uuid": "4d75e9a6-0f9e-4dca-92e4-7e3a72a86dd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011SQg6ngdijte7GiBGM8pvM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2547,
      "cache_read_input_tokens": 58468,
      "output_tokens": 186,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2547,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 186,
          "cache_read_input_tokens": 58468,
          "cache_creation_input_tokens": 2547,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2547
          },
          "type": "message"
        }
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

_source line 36 · 2026-05-21T15:17:33.155Z_

Good, I have all the data needed. Let me now write the report.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4d75e9a6-0f9e-4dca-92e4-7e3a72a86dd5",
  "isSidechain": false,
  "requestId": "req_011CbFwGHyTVBwk4DJ9XrqFb",
  "type": "assistant",
  "uuid": "8098e5d8-cc33-488f-9596-5823b47e1957",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011SQg6ngdijte7GiBGM8pvM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2547,
      "cache_read_input_tokens": 58468,
      "output_tokens": 186,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2547,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 186,
          "cache_read_input_tokens": 58468,
          "cache_creation_input_tokens": 2547,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2547
          },
          "type": "message"
        }
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

_source line 37 · 2026-05-21T15:17:33.766Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CdwQBrJHVNHNWkMVVkSpix`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex",
  "offset": 302,
  "limit": 6
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8098e5d8-cc33-488f-9596-5823b47e1957",
  "isSidechain": false,
  "requestId": "req_011CbFwGHyTVBwk4DJ9XrqFb",
  "type": "assistant",
  "uuid": "5a1ddc9c-00d8-46a1-a509-9a88220fe422",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011SQg6ngdijte7GiBGM8pvM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2547,
      "cache_read_input_tokens": 58468,
      "output_tokens": 186,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2547,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 186,
          "cache_read_input_tokens": 58468,
          "cache_creation_input_tokens": 2547,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2547
          },
          "type": "message"
        }
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

_source line 38 · 2026-05-21T15:17:33.774Z_

<details><summary>↩ Tool result · `toolu_01CdwQBrJHVNHNWkMVVkSpix`</summary>

```text
302	
303	\paragraph{(c) Relaxed matching does not rescue \cwm{}.}
304	Relaxed matching (tolerating format deviations, L0--L4) \emph{decreases} \cwm{} accuracy: 58.04\%$\to$56.98\% (seed 42) and 59.09\%$\to$55.91\% (seed 123). Unparseable predictions default to the majority class (pass, 72.96\%), which outperforms the model's own parseable predictions (42--53\%). The divergence widens from 26\pp{} to 28\pp{} under relaxed matching. This rules out the hypothesis that parsing strictness inflates the observed gap. Constrained decoding~\cite{willard2023outlines} could enforce format compliance but would not address the semantic accuracy deficit among parseable outputs.
305	
306	\paragraph{(d) Variance compression.}
307	\cwm{}'s 5-seed standard deviation (0.37\pp{}) is lower than \cls{} (0.78\pp{}) and \traj{} (0.97\pp{}) at function level. If \cwm{} performance is capped by output-format constraints at a given complexity level, seed-to-seed variability is compressed relative to formulations whose performance depends more on learned representations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5a1ddc9c-00d8-46a1-a509-9a88220fe422",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "1238ff36-90f0-4650-9c93-ee44193b811c",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/appendix.tex",
      "content": "\n\\paragraph{(c) Relaxed matching does not rescue \\cwm{}.}\nRelaxed matching (tolerating format deviations, L0--L4) \\emph{decreases} \\cwm{} accuracy: 58.04\\%$\\to$56.98\\% (seed 42) and 59.09\\%$\\to$55.91\\% (seed 123). Unparseable predictions default to the majority class (pass, 72.96\\%), which outperforms the model's own parseable predictions (42--53\\%). The divergence widens from 26\\pp{} to 28\\pp{} under relaxed matching. This rules out the hypothesis that parsing strictness inflates the observed gap. Constrained decoding~\\cite{willard2023outlines} could enforce format compliance but would not address the semantic accuracy deficit among parseable outputs.\n\n\\paragraph{(d) Variance compression.}\n\\cwm{}'s 5-seed standard deviation (0.37\\pp{}) is lower than \\cls{} (0.78\\pp{}) and \\traj{} (0.97\\pp{}) at function level. If \\cwm{} performance is capped by output-format constraints at a given complexity level, seed-to-seed variability is compressed relative to formulations whose performance depends more on learned representations.",
      "numLines": 6,
      "startLine": 302,
      "totalLines": 464
    }
  },
  "sourceToolAssistantUUID": "5a1ddc9c-00d8-46a1-a509-9a88220fe422",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-21T15:17:37.080Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01JQYCg8LmmB3EhAZsjRZ8yY`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/",
  "description": "Check artifacts directory exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1238ff36-90f0-4650-9c93-ee44193b811c",
  "isSidechain": false,
  "requestId": "req_011CbFwGbkY5DyZmsE8FgoPD",
  "type": "assistant",
  "uuid": "d9234aee-998e-4137-bf72-4bea74b81aef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RrP81phY8eWfpnaEiiBbag",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 520,
      "cache_read_input_tokens": 61015,
      "output_tokens": 105,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 520,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 105,
          "cache_read_input_tokens": 61015,
          "cache_creation_input_tokens": 520,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 520
          },
          "type": "message"
        }
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

_source line 40 · 2026-05-21T15:17:37.239Z_

<details><summary>↩ Tool result · `toolu_01JQYCg8LmmB3EhAZsjRZ8yY`</summary>

```text
4b_8b_cls_cwm_paired_bootstrap_corrected.json
4b_eval_hang_analysis.md
D132-cwm-s123-e2-seq2048
D133_diagnosis.md
D138_data_investigation.md
_project
all_experiments_parsed.json
analysis_5paired_bootstrap.py
bf16_only_tost.json
bibliography_audit_report.json
bibliography_candidates.yaml
block-corr-empirical
block_correlation_analysis.py
ckpt6315_eval_analysis.md
cls4b-v5-ckpt4400-val5120-eval
cls8b-block-correlation-empirical
cls8b-s42-resume-ckpt3600-mutation
cls8b_s42_ckpt3600_per_mutation_pr.json
cls8b_s42_ckpt3600_per_test_pr_bucketed.json
cls8b_seed123_ckpt3000_val_eval_pending.md
cls_multiseed_summary.json
cls_multiseed_table.md
cls_v4_s123_config_comparison.md
cls_v5_cwm_epoch2_launch_config.md
comprehensive_results_summary.md
comprehensive_test_results.md
cwm-rank32-ablation-v2
cwm-rank32-alpha64-ablation
cwm4b_mutation_breakdown.json
cwm8b_seed123_analysis.txt
cwm8b_shard_progress.md
cwm_data_fill_checklist.md
cwm_error_mode_analysis.md
cwm_format_collapse_paragraph.md
cwm_overfitting_analysis.md
cwm_rank32_eval_command.sh
cwm_rank64_train_command.sh
cwm_v6_diagnosis.md
cwm_v6_health_check.md
d008_eval_commands.md
d076_val_unparseable_root_cause.md
d077_fix_report.md
deepseek-cls-repo-v5-ckpt2105-eval-analysis.md
deepseek-cwm-repo-s123-train
deepseek-cwm-repo-s456-train
deepseek-traj-func
deepseek-traj-func-v2
deepseek_func_icc_result.md
deepseek_func_summary.json
deepseek_training_analysis.md
deepseek_traj_per_seed_analysis.md
deepseek_zero_shot.json
diag_cls_v4.md
diag_cwm_v10.md
diag_server_failures_20260516.md
diagnose_deepseek_cwm_s123.md
diagnose_exp-downsample-cls-func-v3-eval.md
diagnosis_cwm_v12_cls_8b.md
dream_reports
efficiency_benchmark.json
error_analysis_data.md
error_complementarity_deepseek.json
error_overlap_matched_seed.json
eval_pipeline_prep.md
eval_readiness_report.md
eval_repo_cls.py
eval_repo_cls_v2.py
eval_status_check_20260514.md
experiment_status_check_loop19.md
extract_predictions_generic.py
f1-macro-audit.md
f1_macro_summary.json
few_shot_baseline.json
fig1_reformulation.pdf
fig1_reformulation.png
fig1_reformulation.py
fig2_gap_amplification.pdf
fig2_gap_amplification.png
fig2_gap_amplification.py
fig3_oracle_stratified.pdf
fig3_oracle_stratified.png
fig3_oracle_stratified.py
figure2_v2.png
figures
gpu_status_20260517.md
holm_bonferroni.py
holm_bonferroni_results.json
inference_benchmark_results.json
lr_verification.json
manifest.yaml
merge_cwm8b_shards.py
multi_seed_test_curves.json
mutation_comparison_summary.json
mutation_comparison_summary.md
mutation_type_accuracy.csv
mutation_type_distribution.json
mvp-a-oracle-sim
mvp-b-data-prep
negative_results_analysis.md
oracle-f2p-stratified
oracle_frontier_dual_icc.md
oracle_icc_sensitivity.json
oracle_icc_sensitivity.pdf
oracle_icc_sensitivity.png
p2p-regression-rate
paper_consistency_audit.md
paper_materials.md
paper_number_audit.md
parse_all_experiments.py
progress_check_20260514.md
qualitative_cls_error_examples.json
qualitative_cwm_examples.json
qwen3-8b-cwm-repo-s42-ckpt400-seq4096-eval
qwen3-8b-traj-func-s123
qwen3-8b-traj-func-s42
qwen3-8b-traj-repo-s42-v2
qwen3-8b-traj-repo-s42-v2-analysis.md
qwen3_8b_3shot_repo_baseline_result.json
qwen3_8b_traj_s123_eval.json
qwen3_8b_traj_s42_eval.json
qwen3_traj_repo_launch_config.md
rank_ablation_chart.pdf
rank_ablation_chart.png
rank_ablation_data.json
rank_ablation_table.tex
re_repair_experiment_design.md
re_repair_phase0_results.md
rebuttal_framework.md
reference_audit.md
reference_audit_report.md
registry_f1_metrics.json
relaxed_matching_results.csv
repo-eval-precheck.md
repo_8b_training_plan.md
repo_level_failure_diagnosis.md
review_issues.yaml
review_reports
run_8b_eval.sh
run_val_sweep.sh
scenario_a_templates.md
seed123_launch_configs.md
seed123_launch_plan.md
supplementary_completeness_audit.md
supplementary_statistics.txt
swebench_pipeline_design.md
three_relay_commands.md
tost_margin_sweep_v2_results.json
tost_sensitivity.json
training_progress_20260512.md
training_progress_check_20260514.md
training_status_20260515.md
traj-v2-results.md
traj_accuracy_investigation.json
traj_complementarity_analysis.json
val_sweep_compilation.md
val_sweep_status.json
val_test_distribution_analysis.md
val_truncation_label_bias_analysis.md
variant_level_all_configs.md
variant_level_verified_results.md
westd_48478_readiness.md
westd_status_loop14.md
westd_status_loop17.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d9234aee-998e-4137-bf72-4bea74b81aef",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "4da21806-afc5-4d73-a07e-4a0f71aecc45",
  "toolUseResult": {
    "stdout": "4b_8b_cls_cwm_paired_bootstrap_corrected.json\n4b_eval_hang_analysis.md\nD132-cwm-s123-e2-seq2048\nD133_diagnosis.md\nD138_data_investigation.md\n_project\nall_experiments_parsed.json\nanalysis_5paired_bootstrap.py\nbf16_only_tost.json\nbibliography_audit_report.json\nbibliography_candidates.yaml\nblock-corr-empirical\nblock_correlation_analysis.py\nckpt6315_eval_analysis.md\ncls4b-v5-ckpt4400-val5120-eval\ncls8b-block-correlation-empirical\ncls8b-s42-resume-ckpt3600-mutation\ncls8b_s42_ckpt3600_per_mutation_pr.json\ncls8b_s42_ckpt3600_per_test_pr_bucketed.json\ncls8b_seed123_ckpt3000_val_eval_pending.md\ncls_multiseed_summary.json\ncls_multiseed_table.md\ncls_v4_s123_config_comparison.md\ncls_v5_cwm_epoch2_launch_config.md\ncomprehensive_results_summary.md\ncomprehensive_test_results.md\ncwm-rank32-ablation-v2\ncwm-rank32-alpha64-ablation\ncwm4b_mutation_breakdown.json\ncwm8b_seed123_analysis.txt\ncwm8b_shard_progress.md\ncwm_data_fill_checklist.md\ncwm_error_mode_analysis.md\ncwm_format_collapse_paragraph.md\ncwm_overfitting_analysis.md\ncwm_rank32_eval_command.sh\ncwm_rank64_train_command.sh\ncwm_v6_diagnosis.md\ncwm_v6_health_check.md\nd008_eval_commands.md\nd076_val_unparseable_root_cause.md\nd077_fix_report.md\ndeepseek-cls-repo-v5-ckpt2105-eval-analysis.md\ndeepseek-cwm-repo-s123-train\ndeepseek-cwm-repo-s456-train\ndeepseek-traj-func\ndeepseek-traj-func-v2\ndeepseek_func_icc_result.md\ndeepseek_func_summary.json\ndeepseek_training_analysis.md\ndeepseek_traj_per_seed_analysis.md\ndeepseek_zero_shot.json\ndiag_cls_v4.md\ndiag_cwm_v10.md\ndiag_server_failures_20260516.md\ndiagnose_deepseek_cwm_s123.md\ndiagnose_exp-downsample-cls-func-v3-eval.md\ndiagnosis_cwm_v12_cls_8b.md\ndream_reports\nefficiency_benchmark.json\nerror_analysis_data.md\nerror_complementarity_deepseek.json\nerror_overlap_matched_seed.json\neval_pipeline_prep.md\neval_readiness_report.md\neval_repo_cls.py\neval_repo_cls_v2.py\neval_status_check_20260514.md\nexperiment_status_check_loop19.md\nextract_predictions_generic.py\nf1-macro-audit.md\nf1_macro_summary.json\nfew_shot_baseline.json\nfig1_reformulation.pdf\nfig1_reformulation.png\nfig1_reformulation.py\nfig2_gap_amplification.pdf\nfig2_gap_amplification.png\nfig2_gap_amplification.py\nfig3_oracle_stratified.pdf\nfig3_oracle_stratified.png\nfig3_oracle_stratified.py\nfigure2_v2.png\nfigures\ngpu_status_20260517.md\nholm_bonferroni.py\nholm_bonferroni_results.json\ninference_benchmark_results.json\nlr_verification.json\nmanifest.yaml\nmerge_cwm8b_shards.py\nmulti_seed_test_curves.json\nmutation_comparison_summary.json\nmutation_comparison_summary.md\nmutation_type_accuracy.csv\nmutation_type_distribution.json\nmvp-a-oracle-sim\nmvp-b-data-prep\nnegative_results_analysis.md\noracle-f2p-stratified\noracle_frontier_dual_icc.md\noracle_icc_sensitivity.json\noracle_icc_sensitivity.pdf\noracle_icc_sensitivity.png\np2p-regression-rate\npaper_consistency_audit.md\npaper_materials.md\npaper_number_audit.md\nparse_all_experiments.py\nprogress_check_20260514.md\nqualitative_cls_error_examples.json\nqualitative_cwm_examples.json\nqwen3-8b-cwm-repo-s42-ckpt400-seq4096-eval\nqwen3-8b-traj-func-s123\nqwen3-8b-traj-func-s42\nqwen3-8b-traj-repo-s42-v2\nqwen3-8b-traj-repo-s42-v2-analysis.md\nqwen3_8b_3shot_repo_baseline_result.json\nqwen3_8b_traj_s123_eval.json\nqwen3_8b_traj_s42_eval.json\nqwen3_traj_repo_launch_config.md\nrank_ablation_chart.pdf\nrank_ablation_chart.png\nrank_ablation_data.json\nrank_ablation_table.tex\nre_repair_experiment_design.md\nre_repair_phase0_results.md\nrebuttal_framework.md\nreference_audit.md\nreference_audit_report.md\nregistry_f1_metrics.json\nrelaxed_matching_results.csv\nrepo-eval-precheck.md\nrepo_8b_training_plan.md\nrepo_level_failure_diagnosis.md\nreview_issues.yaml\nreview_reports\nrun_8b_eval.sh\nrun_val_sweep.sh\nscenario_a_templates.md\nseed123_launch_configs.md\nseed123_launch_plan.md\nsupplementary_completeness_audit.md\nsupplementary_statistics.txt\nswebench_pipeline_design.md\nthree_relay_commands.md\ntost_margin_sweep_v2_results.json\ntost_sensitivity.json\ntraining_progress_20260512.md\ntraining_progress_check_20260514.md\ntraining_status_20260515.md\ntraj-v2-results.md\ntraj_accuracy_investigation.json\ntraj_complementarity_analysis.json\nval_sweep_compilation.md\nval_sweep_status.json\nval_test_distribution_analysis.md\nval_truncation_label_bias_analysis.md\nvariant_level_all_configs.md\nvariant_level_verified_results.md\nwestd_48478_readiness.md\nwestd_status_loop14.md\nwestd_status_loop17.md",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "d9234aee-998e-4137-bf72-4bea74b81aef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 41_

```json
{
  "type": "last-prompt",
  "leafUuid": "4da21806-afc5-4d73-a07e-4a0f71aecc45",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Runtime record

_source line 42_

```json
{
  "type": "ai-title",
  "aiTitle": "Scan appendix.tex for residual issues",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Tool call

_source line 43 · 2026-05-21T15:18:24.632Z_

<details open><summary>🔧 Tool call — Write · `toolu_01Fot11RX3LNaB6gC2gwGcUw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/appendix_cleanup_report.md",
  "content": "# Appendix Cleanup Scan Report\n\n## 1. Placeholder/Tentative Wording\n\n| Line | Current Text | Issue | Suggested Fix |\n|------|-------------|-------|---------------|\n| 67 | `\\footnote{These majority-voting values were computed from an unverified checkpoint and may differ slightly from the val-best checkpoint results.}` | \"unverified checkpoint\" + \"may differ\" — pre-submission hedge that signals unfinished verification | Either verify against val-best checkpoint and update numbers, or remove footnote if difference is negligible |\n| 110 | `\\cwm{} 4B per-mutation overall accuracy unavailable except gold` | \"unavailable\" — missing data acknowledged in table caption | Compute the missing values or explicitly state why they cannot be computed (e.g., \"not reported due to …\") |\n| 463 | `Repo-level \\cls{}--\\traj{} comparison is tentative due to configuration and granularity differences.` | \"tentative\" — acceptable as scientific qualifier but weakens the claim | Consider replacing with \"should be interpreted with caution\" or similar phrasing that doesn't sound like the analysis is incomplete |\n\n**Note:** `\\tbd{}` appears in **experiments.tex** Table 2 (lines 120–121, CWM columns for Qwen3-8B and DeepSeek-6.7B) but **not** in appendix.tex. The appendix implicitly depends on these missing values (e.g., paragraph (g) references CWM repo-level results).\n\n## 2. Inconsistencies with Main Text\n\n| Item | Main Text Value | Appendix Value | Line | Fix |\n|------|----------------|----------------|------|-----|\n| Parseable-only accuracy range | **38–43%** (experiments.tex:174, appendix ¶(g):322) | **42–53%** (¶(c):304) | 304 | Inconsistent range. ¶(g) and main text agree on 38–43%. ¶(c) uses 42–53% — if this is the cross-seed range for 4B specifically (seed 42 ≈ 42.88%, seed 123 ≈ 53%?), state the scope explicitly. Otherwise correct to match. |\n| CLS–CWM gap under relaxed matching | Standard gap = 25.59pp (experiments.tex:135, 4B s42) | \"divergence widens from 26pp to 28pp\" (¶(c):304) | 304 | 25.59pp rounds to ~26pp — OK. But \"28pp\": CLS 83.63% − CWM-relaxed 56.98% = 26.65pp, not 28pp. The 28pp might use seed 123 (83.63 − 55.91 = 27.72 ≈ 28pp), but CLS 83.63% is seed 42 only. Verify computation and clarify which seed(s) the \"26→28\" refers to. |\n| Unparseable rate (8B) | **73.8%** (experiments.tex:160) | **74%** (threats ¶:449) | 449 | Minor rounding: 73.8% vs 74%. Standardize to one value (73.8% preferred as more precise). |\n| 19–26pp gap | 19–26pp (experiments.tex:135, conclusion:4) | 19–26pp (threats:457) | — | ✅ Consistent |\n| z = −23.7 | experiments.tex:164 | appendix:432 | — | ✅ Consistent |\n| Oracle 90.63% | introduction:17, experiments.tex:178 | appendix:292, 298 | — | ✅ Consistent |\n| 217× throughput | experiments.tex:176, conclusion:4 | appendix:332 | — | ✅ Consistent |\n| ~370 GPU-hours | (main text via git history) | appendix:251 | — | ✅ Consistent |\n| TOST p = 0.007 | experiments.tex:98, conclusion:4 | appendix:358, 463 | — | ✅ Consistent |\n\n## 3. Redundancy / Pruning Opportunities\n\n| Section | Lines | Issue | Recommendation |\n|---------|-------|-------|----------------|\n| ¶(g) Failed interventions | 317–326 | Summarizes four interventions, each already detailed in dedicated sections: rank ablation (§B:44–64), majority voting (§B:66–67), relaxed matching (¶(c):303–304), model scaling (main text §4.4) | Useful as synthesis. **Keep**, but shorten each bullet to 1 line with cross-refs instead of repeating numbers. Currently ~10 lines of near-duplicate data. |\n| ¶(h) Per-mutation scaling | 328–329 | Recapitulates Table 8 (§D) and Table 12 (§F) findings narratively | **Keep** as narrative synthesis. No action needed — adds interpretive value over raw tables. |\n| Threats §J (full) | 442–457 | Overlaps with main text §5.5 (experiments.tex:180–183). The final paragraph (line 457) repeats \"19–26pp exceeds any single assessed confound\" verbatim from the main text summary. | Expected: appendix is the full version, main text is the summary. **No pruning needed**, but consider removing the final summary paragraph (lines 457–end) since it's identical to the main text version — readers who reach the appendix have already read it. |\n| Oracle §A (lines 36–39) sensitivity paragraph | 38–39 | Speculative paragraph about repo-level ICC yielding \"even larger gap\" — no quantitative analysis provided, just a qualitative extrapolation | Either compute the repo-level oracle advantage or delete. Currently a soft claim without evidence. |\n\n## Summary\n\n**Critical (fix before submission):**\n1. **Line 67**: \"unverified checkpoint\" footnote on majority-voting numbers — either verify or remove. This is the only item that signals incomplete work to a reviewer.\n2. **Line 304**: Parseable-only accuracy \"42–53%\" contradicts \"38–43%\" used in ¶(g) and main text. Verify the correct range and make all three locations consistent.\n3. **Line 304**: \"26pp to 28pp\" gap claim — arithmetic doesn't cleanly match (standard gap = 25.59pp, relaxed = 26.65pp for seed 42). Verify computation.\n\n**Minor (nice to fix):**\n4. **Line 449**: Standardize unparseable rate to 73.8% (not 74%).\n5. **Line 110**: \"unavailable\" in Table 8 caption — consider rewording to explain *why*.\n6. **Lines 317–326**: ¶(g) bullets can be compressed to cross-refs (~5 lines saved).\n7. **Line 463**: \"tentative\" is acceptable hedging but could be reworded.\n\n**No action needed:** All major numerical claims (19–26pp, z = −23.7, oracle 90.63%/95.83%, 217×, ~370 GPU-hours, TOST p = 0.007) are consistent between appendix and main text.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4da21806-afc5-4d73-a07e-4a0f71aecc45",
  "isSidechain": false,
  "requestId": "req_011CbFwGrYHRND9oXGYKzteG",
  "type": "assistant",
  "uuid": "160d0b22-58c9-45cd-89df-5e19a4bc19af",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ps3rUmN7eCvjBdVKEjbRh3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1850,
      "cache_read_input_tokens": 61535,
      "output_tokens": 1874,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1850,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1874,
          "cache_read_input_tokens": 61535,
          "cache_creation_input_tokens": 1850,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1850
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-21T15:18:24.664Z_

<details><summary>↩ Tool result · `toolu_01Fot11RX3LNaB6gC2gwGcUw`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/appendix_cleanup_report.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "160d0b22-58c9-45cd-89df-5e19a4bc19af",
  "isSidechain": false,
  "promptId": "ff87a363-85f3-40d4-98bb-c63511d84ab0",
  "type": "user",
  "uuid": "a6686538-9085-4956-9412-143191ad3dce",
  "toolUseResult": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/appendix_cleanup_report.md",
    "content": "# Appendix Cleanup Scan Report\n\n## 1. Placeholder/Tentative Wording\n\n| Line | Current Text | Issue | Suggested Fix |\n|------|-------------|-------|---------------|\n| 67 | `\\footnote{These majority-voting values were computed from an unverified checkpoint and may differ slightly from the val-best checkpoint results.}` | \"unverified checkpoint\" + \"may differ\" — pre-submission hedge that signals unfinished verification | Either verify against val-best checkpoint and update numbers, or remove footnote if difference is negligible |\n| 110 | `\\cwm{} 4B per-mutation overall accuracy unavailable except gold` | \"unavailable\" — missing data acknowledged in table caption | Compute the missing values or explicitly state why they cannot be computed (e.g., \"not reported due to …\") |\n| 463 | `Repo-level \\cls{}--\\traj{} comparison is tentative due to configuration and granularity differences.` | \"tentative\" — acceptable as scientific qualifier but weakens the claim | Consider replacing with \"should be interpreted with caution\" or similar phrasing that doesn't sound like the analysis is incomplete |\n\n**Note:** `\\tbd{}` appears in **experiments.tex** Table 2 (lines 120–121, CWM columns for Qwen3-8B and DeepSeek-6.7B) but **not** in appendix.tex. The appendix implicitly depends on these missing values (e.g., paragraph (g) references CWM repo-level results).\n\n## 2. Inconsistencies with Main Text\n\n| Item | Main Text Value | Appendix Value | Line | Fix |\n|------|----------------|----------------|------|-----|\n| Parseable-only accuracy range | **38–43%** (experiments.tex:174, appendix ¶(g):322) | **42–53%** (¶(c):304) | 304 | Inconsistent range. ¶(g) and main text agree on 38–43%. ¶(c) uses 42–53% — if this is the cross-seed range for 4B specifically (seed 42 ≈ 42.88%, seed 123 ≈ 53%?), state the scope explicitly. Otherwise correct to match. |\n| CLS–CWM gap under relaxed matching | Standard gap = 25.59pp (experiments.tex:135, 4B s42) | \"divergence widens from 26pp to 28pp\" (¶(c):304) | 304 | 25.59pp rounds to ~26pp — OK. But \"28pp\": CLS 83.63% − CWM-relaxed 56.98% = 26.65pp, not 28pp. The 28pp might use seed 123 (83.63 − 55.91 = 27.72 ≈ 28pp), but CLS 83.63% is seed 42 only. Verify computation and clarify which seed(s) the \"26→28\" refers to. |\n| Unparseable rate (8B) | **73.8%** (experiments.tex:160) | **74%** (threats ¶:449) | 449 | Minor rounding: 73.8% vs 74%. Standardize to one value (73.8% preferred as more precise). |\n| 19–26pp gap | 19–26pp (experiments.tex:135, conclusion:4) | 19–26pp (threats:457) | — | ✅ Consistent |\n| z = −23.7 | experiments.tex:164 | appendix:432 | — | ✅ Consistent |\n| Oracle 90.63% | introduction:17, experiments.tex:178 | appendix:292, 298 | — | ✅ Consistent |\n| 217× throughput | experiments.tex:176, conclusion:4 | appendix:332 | — | ✅ Consistent |\n| ~370 GPU-hours | (main text via git history) | appendix:251 | — | ✅ Consistent |\n| TOST p = 0.007 | experiments.tex:98, conclusion:4 | appendix:358, 463 | — | ✅ Consistent |\n\n## 3. Redundancy / Pruning Opportunities\n\n| Section | Lines | Issue | Recommendation |\n|---------|-------|-------|----------------|\n| ¶(g) Failed interventions | 317–326 | Summarizes four interventions, each already detailed in dedicated sections: rank ablation (§B:44–64), majority voting (§B:66–67), relaxed matching (¶(c):303–304), model scaling (main text §4.4) | Useful as synthesis. **Keep**, but shorten each bullet to 1 line with cross-refs instead of repeating numbers. Currently ~10 lines of near-duplicate data. |\n| ¶(h) Per-mutation scaling | 328–329 | Recapitulates Table 8 (§D) and Table 12 (§F) findings narratively | **Keep** as narrative synthesis. No action needed — adds interpretive value over raw tables. |\n| Threats §J (full) | 442–457 | Overlaps with main text §5.5 (experiments.tex:180–183). The final paragraph (line 457) repeats \"19–26pp exceeds any single assessed confound\" verbatim from the main text summary. | Expected: appendix is the full version, main text is the summary. **No pruning needed**, but consider removing the final summary paragraph (lines 457–end) since it's identical to the main text version — readers who reach the appendix have already read it. |\n| Oracle §A (lines 36–39) sensitivity paragraph | 38–39 | Speculative paragraph about repo-level ICC yielding \"even larger gap\" — no quantitative analysis provided, just a qualitative extrapolation | Either compute the repo-level oracle advantage or delete. Currently a soft claim without evidence. |\n\n## Summary\n\n**Critical (fix before submission):**\n1. **Line 67**: \"unverified checkpoint\" footnote on majority-voting numbers — either verify or remove. This is the only item that signals incomplete work to a reviewer.\n2. **Line 304**: Parseable-only accuracy \"42–53%\" contradicts \"38–43%\" used in ¶(g) and main text. Verify the correct range and make all three locations consistent.\n3. **Line 304**: \"26pp to 28pp\" gap claim — arithmetic doesn't cleanly match (standard gap = 25.59pp, relaxed = 26.65pp for seed 42). Verify computation.\n\n**Minor (nice to fix):**\n4. **Line 449**: Standardize unparseable rate to 73.8% (not 74%).\n5. **Line 110**: \"unavailable\" in Table 8 caption — consider rewording to explain *why*.\n6. **Lines 317–326**: ¶(g) bullets can be compressed to cross-refs (~5 lines saved).\n7. **Line 463**: \"tentative\" is acceptable hedging but could be reworded.\n\n**No action needed:** All major numerical claims (19–26pp, z = −23.7, oracle 90.63%/95.83%, 217×, ~370 GPU-hours, TOST p = 0.007) are consistent between appendix and main text.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  },
  "sourceToolAssistantUUID": "160d0b22-58c9-45cd-89df-5e19a4bc19af",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 45 · 2026-05-21T15:18:33.025Z_

报告已写入 `artifacts/appendix_cleanup_report.md`。

核心发现：

**3 个需修复项：**
1. **Line 67** — majority-voting 脚注承认用了 "unverified checkpoint"，submission 前必须验证或删除
2. **Line 304 ¶(c)** — parseable-only accuracy 写 "42–53%"，与 ¶(g) 和主文的 "38–43%" 矛盾
3. **Line 304 ¶(c)** — "divergence widens from 26pp to 28pp" 算术对不上（seed 42 标准 gap = 25.59pp，relaxed = 26.65pp，不是 28pp）

**4 个小问题：** 449 行 unparseable rate 74% vs 73.8% 取整不一致；Table 8 caption "unavailable" 措辞；¶(g) 可压缩为交叉引用省 ~5 行；Extended Limitations 的 "tentative" 可换更强措辞。

主要数字（19–26pp、z=−23.7、oracle 90.63%/95.83%、217×、~370 GPU-hours、TOST p=0.007）全部一致，无问题。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a6686538-9085-4956-9412-143191ad3dce",
  "isSidechain": false,
  "requestId": "req_011CbFwLMKyrhgwbFfvCPVUF",
  "type": "assistant",
  "uuid": "49e83733-a77f-4966-8671-0d7368e44779",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xj1dQ5ZaVN5ZTJDRkDKkej",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1932,
      "cache_read_input_tokens": 63385,
      "output_tokens": 348,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1932,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 348,
          "cache_read_input_tokens": 63385,
          "cache_creation_input_tokens": 1932,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1932
          },
          "type": "message"
        }
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

_source line 46_

```json
{
  "type": "last-prompt",
  "leafUuid": "49e83733-a77f-4966-8671-0d7368e44779",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

### Runtime record

_source line 47_

```json
{
  "type": "ai-title",
  "aiTitle": "Scan appendix.tex for residual issues",
  "sessionId": "f2fe2b10-7f45-45b0-92d7-5ac890a91bc1"
}
```

---

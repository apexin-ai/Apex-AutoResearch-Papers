# Research conversation: <project_context> # 项目: gen-depth-contamination ## 运行环境 - 服务器名: cqa1-22115 - SSH 账户: root（调用 ssh_execute / submit_traini

**Generational Depth Estimation of Recursive Synthetic Text: Measuring the Discrimination Boundary (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 98
- **Recorded user turns:** 1
- **Tool calls:** 25
- **Original source:** `logs/chats/exported-trajectories/account-2/34d999f9-ba08-4dc3-8d75-ac2750aed5c6.jsonl`
- **Structured JSON:** [`d810a0f15c5775839b0e.json`](../../sessions/d8/d810a0f15c5775839b0e.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-23T11:01:42.450Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-23T11:01:42.450Z",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "content": "&lt;project_context>\n# 项目: gen-depth-contamination\n\n## 运行环境\n- 服务器名: cqa1-22115\n- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account=\"root\"）\n- SSH 连接命令: ssh cqa1-22115  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/autodl-tmp/gen-depth-contamination\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n全文数据审计：Table 2 + Table 10 + Table 1。\n\n你的任务是核对论文中每个数值到 registry 实验记录，找出所有不匹配项。\n\n**方法**：用 read_registry 获取所有实验数据，然后逐个核对。\n\n**Table 1**（method.tex, tab:setup）：\n- 检查 6 个配置的模型名称和参数量是否正确\n\n**Table 2**（experiments_c1.tex, tab:kstar_ci, lines 19-36）：\n- 5 个配置（Qwen-rw, Pythia, OLMo, Qwen-cont, Qwen-7B）的 AUC 值\n- 每个 depth pair (0v1, 1v2, 2v3, 3v4, 4v5) 的 AUC 和 bootstrap CI\n- 追溯到 registry 的 exp_id，确认数值匹配\n- 关键 registry IDs（从之前分析已知）：\n  - exp_001_pythia_depth: Pythia (Qwen cross-scored)\n  - exp_14b_c4: 可能是 Qwen 相关\n  - 查找 Qwen-rw, Qwen-cont, OLMo, Qwen-7B 对应的 exp_ids\n\n**Table 10**（appendix.tex, tab:kstar_ci_extended, lines 131-148）：\n- 10 个配置的 AUC 值\n- 与 Table 2 的重叠配置必须完全一致（刚修过 Pythia）\n- 新增配置（Qwen-base, LLaMA-8B, Mistral-7B, Pythia-6.9B, Gemma-2B）各自追溯到 registry\n\n**论文文件路径**：\n- /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex\n- /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex\n- /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex\n\n**输出格式**（每个值）：\n| 表格 | 配置 | Depth Pair | 论文值 | Registry exp_id | Registry 值 | 匹配 |\n\n列出所有不匹配项及修复方案。如果发现不匹配，直接用 Edit 工具修复论文中的错误值。"
}
```

---

### Runtime record

_source line 2 · 2026-05-23T11:01:42.453Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-23T11:01:42.453Z",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

## Round 1

96 recorded events

### User

_source line 3 · 2026-05-23T11:01:42.487Z_

&lt;project_context>
# 项目: gen-depth-contamination

## 运行环境
- 服务器名: cqa1-22115
- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account="root"）
- SSH 连接命令: ssh cqa1-22115  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/autodl-tmp/gen-depth-contamination


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
全文数据审计：Table 2 + Table 10 + Table 1。

你的任务是核对论文中每个数值到 registry 实验记录，找出所有不匹配项。

**方法**：用 read_registry 获取所有实验数据，然后逐个核对。

**Table 1**（method.tex, tab:setup）：
- 检查 6 个配置的模型名称和参数量是否正确

**Table 2**（experiments_c1.tex, tab:kstar_ci, lines 19-36）：
- 5 个配置（Qwen-rw, Pythia, OLMo, Qwen-cont, Qwen-7B）的 AUC 值
- 每个 depth pair (0v1, 1v2, 2v3, 3v4, 4v5) 的 AUC 和 bootstrap CI
- 追溯到 registry 的 exp_id，确认数值匹配
- 关键 registry IDs（从之前分析已知）：
  - exp_001_pythia_depth: Pythia (Qwen cross-scored)
  - exp_14b_c4: 可能是 Qwen 相关
  - 查找 Qwen-rw, Qwen-cont, OLMo, Qwen-7B 对应的 exp_ids

**Table 10**（appendix.tex, tab:kstar_ci_extended, lines 131-148）：
- 10 个配置的 AUC 值
- 与 Table 2 的重叠配置必须完全一致（刚修过 Pythia）
- 新增配置（Qwen-base, LLaMA-8B, Mistral-7B, Pythia-6.9B, Gemma-2B）各自追溯到 registry

**论文文件路径**：
- /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex
- /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex
- /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex

**输出格式**（每个值）：
| 表格 | 配置 | Depth Pair | 论文值 | Registry exp_id | Registry 值 | 匹配 |

列出所有不匹配项及修复方案。如果发现不匹配，直接用 Edit 工具修复论文中的错误值。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "cb4ce1fe-679b-4b2d-9896-c9505a761a96",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-23T11:01:42.487Z_

```json
{
  "parentUuid": "cb4ce1fe-679b-4b2d-9896-c9505a761a96",
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
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__update_registry"
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
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__update_registry"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "7497e142-ae88-4733-83a5-06df54a074d5",
  "timestamp": "2026-05-23T11:01:42.487Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-23T11:01:42.487Z_

```json
{
  "parentUuid": "7497e142-ae88-4733-83a5-06df54a074d5",
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
  "uuid": "03cdbc48-14d3-49a2-9728-802a8d881bc9",
  "timestamp": "2026-05-23T11:01:42.487Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-23T11:01:42.487Z_

```json
{
  "parentUuid": "03cdbc48-14d3-49a2-9728-802a8d881bc9",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "6bfe7c9d-3303-451a-8d4d-5c38b7dd5402",
  "timestamp": "2026-05-23T11:01:42.487Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
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
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 8 · 2026-05-23T11:01:45.091Z_

I'll start by reading the registry and the three paper files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6bfe7c9d-3303-451a-8d4d-5c38b7dd5402",
  "isSidechain": false,
  "requestId": "req_011CbKPNpdeEUwmPS9foK1Sj",
  "type": "assistant",
  "uuid": "75ad46a1-f564-44a5-961f-3093950bd597",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JANo4bUDJm9W7oRd2BXhUp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12312,
      "cache_read_input_tokens": 11841,
      "output_tokens": 102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12312,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 102,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12312,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12312
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-23T11:01:45.877Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01FdMawDUmufJC7mAu6SyyGW`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "75ad46a1-f564-44a5-961f-3093950bd597",
  "isSidechain": false,
  "requestId": "req_011CbKPNpdeEUwmPS9foK1Sj",
  "type": "assistant",
  "uuid": "c14fb7c0-476f-4817-8e62-fdd403acee96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JANo4bUDJm9W7oRd2BXhUp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12312,
      "cache_read_input_tokens": 11841,
      "output_tokens": 102,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12312,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 102,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12312,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12312
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-23T11:01:45.886Z_

<details><summary>↩ Tool result · `toolu_01FdMawDUmufJC7mAu6SyyGW`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c14fb7c0-476f-4817-8e62-fdd403acee96",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "046ae3da-035e-448e-85a9-ee852b22acb6",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 22
  },
  "sourceToolAssistantUUID": "c14fb7c0-476f-4817-8e62-fdd403acee96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-23T11:01:48.195Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the registry and all three paper files in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "046ae3da-035e-448e-85a9-ee852b22acb6",
  "isSidechain": false,
  "requestId": "req_011CbKPP5Pf1zgmH6Q6m6bZ1",
  "type": "assistant",
  "uuid": "eb36cf04-6431-4b39-a663-b28986f3f946",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RH1Vc9duTAip2PnkbYXraS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 464,
      "cache_read_input_tokens": 24153,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 350,
          "cache_read_input_tokens": 24153,
          "cache_creation_input_tokens": 464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 464
          },
          "type": "message"
        }
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

_source line 12 · 2026-05-23T11:01:48.698Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01HyLtXKRoP2T7vJB6P82tXB`</summary>

```json
{
  "project": "gen-depth-contamination",
  "limit": 0,
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eb36cf04-6431-4b39-a663-b28986f3f946",
  "isSidechain": false,
  "requestId": "req_011CbKPP5Pf1zgmH6Q6m6bZ1",
  "type": "assistant",
  "uuid": "167e0737-73bc-4ca3-aee7-0ce649ef9109",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RH1Vc9duTAip2PnkbYXraS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 464,
      "cache_read_input_tokens": 24153,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 350,
          "cache_read_input_tokens": 24153,
          "cache_creation_input_tokens": 464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 464
          },
          "type": "message"
        }
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

_source line 13 · 2026-05-23T11:01:49.603Z_

<details><summary>↩ Tool result · `toolu_01HyLtXKRoP2T7vJB6P82tXB`</summary>

```text
Error: result (288,566 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "167e0737-73bc-4ca3-aee7-0ce649ef9109",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "8d8092e5-b9bd-4fc6-871b-488a666bc6d9",
  "toolUseResult": "Error: result (288,566 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp_gemma2b_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T18:00:38.686Z\", \"updated_at\": \"2026-05-23T00:21:06.691Z\", \"hypothesis\": \"Gemma-2-2B 10K sample-size robustness: 5K borderline K*=1 (1v2 AUC=0.5981, just below θ=0.60) should remain K*=1 at 10K, confirming between-sample stability for borderline verdicts. Adds a K*=1 datapoint to the 10K robustness table (currently only K*=2 configs).\", \"spec\": {\"server\": \"cqa1-22115\", \"pid\": 54709, \"gpu\": \"cuda:3\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_gemma2b_10k/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_gemma2b_10k/run.log\", \"completed_at\": \"2026-05-22T23:16:00.183Z\", \"metrics\": {\"K_star_self\": 2, \"K_star_qwen\": 2, \"scorer\": \"Qwen2.5-1.5B-Instruct (cross-scored)\", \"pairwise_auc_self\": {\"0v1\": 0.9817, \"1v2\": 0.643, \"2v3\": 0.555, \"3v4\": 0.5173, \"4v5\": 0.5101}, \"pairwise_auc_qwen\": {\"0v1\": 0.9533, \"1v2\": 0.6099, \"2v3\": 0.5409, \"3v4\": 0.5174, \"4v5\": 0.5158}, \"bootstrap_ci_1v2\": {\"auc_oof\": 0.6099, \"boot_std\": 0.0034, \"ci_95\": [0.6031, 0.6167], \"ci_995_bonferroni_pct\": [0.5998, 0.6192], \"ci_995_bonferroni_norm\": [0.6003, 0.6196], \"perm_p\": 0.0001, \"bonferroni_pass_pct\": false, \"bonferroni_pass_norm\": true}, \"note\": \"5K K*=1 (1v2=0.5981), 10K Qwen cross-scored K*=2 (1v2=0.6099). Bonferroni split: percentile FAIL (0.5998), normal PASS (0.6003). Extremely borderline.\"}}, \"seed_gemma27b_c4_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T10:05:43.080Z\", \"updated_at\": \"2026-05-23T00:00:23.931Z\", \"spec\": {\"server\": \"cqa1-22115\", \"pid\": 26893, \"gpu\": \"cuda:0\"}, \"conclusion\": \"success\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_gemma27b_c4/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_gemma27b_c4/\", \"hypothesis\": \"Gemma-2-27B, the largest model tested, will exhibit K*=2 consistent with smaller models, confirming that generational depth saturation is model-scale-invariant for the surprisal-feature OBD pipeline.\", \"completed_at\": \"2026-05-22T23:06:04.697Z\", \"metrics\": {\"K_star\": 1, \"scorer\": \"Qwen2.5-1.5B-Instruct (cross-scored)\", \"pairwise_auc_self\": {\"0v1\": 0.9695, \"1v2\": 0.6196, \"2v3\": 0.5388, \"3v4\": 0.5069, \"4v5\": 0.5124}, \"pairwise_auc_qwen\": {\"0v1\": 0.8874, \"1v2\": 0.5894}, \"note\": \"Self-scored K*=2 (1v2=0.6196), Qwen cross-scored K*=1 (1v2=0.5894 < θ=0.60). Self→Cross inflation: 1v2 Δ=-3.0pp, 0v1 Δ=-8.2pp.\"}}, \"exp_olmo1b_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T20:05:20.014Z\", \"updated_at\": \"2026-05-22T22:34:48.584Z\", \"hypothesis\": \"OLMo-1B on 10K C4 samples will show saturation at depth K*=1, meaning generation-depth signal is only distinguishable between real (depth-0) and first-generation synthetic text, with deeper depths being indistinguishable from each other.\", \"spec\": {\"command\": \"bash /tmp/exp_olmo1b_10k.sh (Phase1: OLMo-1B continuation gen + Phase2: Qwen scorer)\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"pid\": 66415, \"data_path\": \"data/olmo1b_c4_10k\", \"data_count\": 10000, \"model_name\": \"allenai/OLMo-1B-hf (gen) + Qwen2.5-1.5B-Instruct (scorer)\", \"seed\": 42, \"log_path\": \"/tmp/exp_olmo1b_10k.log\", \"checkpoint_path\": \"results/olmo1b_c4_10k/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T22:34:45.698Z\", \"metrics\": {\"pairwise_auc\": {\"0v1\": 0.9871, \"1v2\": 0.4984, \"2v3\": 0.5059, \"3v4\": 0.5061, \"4v5\": 0.5074}, \"K_star\": 1, \"ordinal_mae\": 1.4145, \"ordinal_accuracy\": 0.3152, \"pairwise_jsd\": {\"0v1\": 0.230018, \"1v2\": 0.001457, \"2v3\": 0.001512, \"3v4\": 0.001413, \"4v5\": 0.001535}, \"top_features\": [\"freq_entropy\", \"surp_d1_mean\", \"freq_kurtosis\", \"surp_d2_mean\", \"surp_d1_skew\"]}}, \"exp_002_olmo_depth\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-12T20:06:24.766Z\", \"updated_at\": \"2026-05-22T22:04:07.552Z\", \"hypothesis\": \"K* 跨模型一致性验证：OLMo-1B 在相同种子数据和解码策略下的 K* 是否与 Qwen2.5-1.5B 一致（K*=2）\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && cd /root/autodl-tmp/gen-depth-contamination && python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/allenai/OLMo-1B-hf --data_dir /root/autodl-tmp/gen-depth-contamination/data_exp002_olmo --results_dir /root/autodl-tmp/gen-depth-contamination/results_exp002_olmo --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"server\": \"autodl-4090d\", \"gpu\": [\"cuda:0\"], \"pid\": \"20225\", \"log_path\": \"~/runs/gen-depth-contamination/exp_002_olmo_depth.log\", \"submitted_at\": \"2026-05-13T00:16:07.960Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp002_olmo\", \"data_count\": 5000, \"model_name\": \"allenai/OLMo-1B-hf\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp002_olmo/\", \"wall_clock_seconds\": 8384.9, \"gpu_hours\": 2.33}, \"reproduce\": {\"finished_at\": \"2026-05-13T02:31:18.880Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T02:31:19.738113+00:00\"}]}, \"metrics\": {\"k_star\": 1, \"pairwise_auc\": {\"0v1\": 0.9861, \"1v2\": 0.5001, \"2v3\": 0.4972, \"3v4\": 0.5034, \"4v5\": 0.4971}, \"scorer\": \"Qwen2.5-1.5B-Instruct\", \"note\": \"Updated to Qwen cross-scoring (D107). Self-scored 1v2=0.6145 K*=2, Qwen-scored 1v2=0.5001 K*=1.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T02:35:52.823Z\", \"parent\": \"exp_001_pythia_depth\"}, \"exp_001_pythia_depth\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-12T20:06:23.803Z\", \"updated_at\": \"2026-05-22T22:04:05.591Z\", \"hypothesis\": \"K* 跨模型一致性验证：Pythia-1.4B 在相同种子数据和解码策略下的 K* 是否与 Qwen2.5-1.5B 一致（K*=2）\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && cd /root/autodl-tmp/gen-depth-contamination && python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/EleutherAI/pythia-1.4b --data_dir /root/autodl-tmp/gen-depth-contamination/data_exp001_pythia --results_dir /root/autodl-tmp/gen-depth-contamination/results_exp001_pythia --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"server\": \"autodl-4090d\", \"gpu\": [\"cuda:0\"], \"pid\": \"17138\", \"log_path\": \"~/runs/gen-depth-contamination/exp_001_pythia_depth.log\", \"submitted_at\": \"2026-05-12T20:50:31.471Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp001_pythia\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp001_pythia/\", \"wall_clock_seconds\": 12344.9, \"gpu_hours\": 3.43}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9722, \"1v2\": 0.6074, \"2v3\": 0.544, \"3v4\": 0.5051, \"4v5\": 0.5079}, \"pairwise_auc_std\": {\"0v1\": 0.0039, \"1v2\": 0.0078, \"2v3\": 0.0067, \"3v4\": 0.0032, \"4v5\": 0.0101}, \"bootstrap_ci\": {\"1v2\": {\"auc_oof\": 0.6072, \"boot_mean\": 0.6073, \"boot_std\": 0.005, \"ci_95\": [0.5975, 0.6172], \"ci_995_bonferroni\": [0.5934, 0.621], \"perm_p\": 0.0001, \"bonferroni_pass\": false}}, \"scorer\": \"Qwen2.5-1.5B-Instruct\", \"note\": \"Updated to Qwen cross-scoring (D107). Self-scored 1v2=0.6539, Qwen-scored 1v2=0.6074.\"}, \"completed_at\": \"2026-05-13T00:16:16.359Z\"}, \"exp_llama8b_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T09:25:55.895Z\", \"updated_at\": \"2026-05-22T20:26:09.870Z\", \"hypothesis\": \"增加 LLaMA-8B C4 样本量从 5k→10k 可将 1v2 bootstrap std 缩小 ~√2 倍，使 Bonferroni 99.5% CI lower bound 恢复到 θ=0.60 以上\", \"spec\": {\"server\": \"cqa1-22115\", \"pid\": 23232, \"checkpoint_path\": \"results/exp_llama8b_10k/\", \"log_path\": \"/tmp/exp_llama8b_10k.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"K_star\": 1, \"AUC_0v1\": 0.9282, \"AUC_1v2\": 0.6148, \"AUC_1v2_oof\": 0.588, \"AUC_2v3\": 0.5247, \"AUC_3v4\": 0.5519, \"AUC_4v5\": 0.5262, \"bootstrap_1v2_oof_auc\": 0.588, \"bootstrap_1v2_95CI\": [0.5809, 0.595], \"bootstrap_1v2_995CI_bonferroni\": [0.5776, 0.5978], \"bonferroni_pass\": false, \"perm_pvalue_1v2\": 0.0001, \"scorer\": \"Qwen2.5-1.5B-Instruct\", \"note\": \"All pairwise AUC from Qwen cross-scoring (Phase 2). Pipeline AUC 1v2=0.6148 (mean-of-folds).\"}, \"completed_at\": \"2026-05-22T19:21:09.215Z\"}, \"exp_pythia14b_c4_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T11:57:18.681Z\", \"updated_at\": \"2026-05-22T14:59:24.436Z\", \"hypothesis\": \"统一所有 K*=2 configs 的样本量至 10K，避免 selective precision boosting 质疑。Pythia-1.4B 5K 已稳定通过 Bonferroni (CI_lower≈0.641>0.60)，10K 为一致性验证。\", \"spec\": {\"command\": \"python3 scripts/run_pipeline.py --model_path pythia-1.4b --num_samples 10000 --max_depth 5 --batch_size 32 --generation_mode continuation + Phase2 Qwen scorer\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:3 (RTX PRO 6000 Blackwell 96GB)\", \"data_path\": \"data/exp_pythia14b_c4_10k\", \"data_count\": 10000, \"model_name\": \"Pythia-1.4B (gen) + Qwen2.5-1.5B-Instruct (scorer)\", \"seed\": 42, \"log_path\": \"/tmp/exp_pythia14b_c4_10k.log\", \"checkpoint_path\": \"results/exp_pythia14b_c4_10k/\"}, \"metrics\": {\"K_star\": 2, \"AUC_0v1\": 0.9712, \"AUC_1v2\": 0.6175, \"AUC_2v3\": 0.5364, \"AUC_3v4\": 0.5134, \"AUC_4v5\": 0.5088, \"bootstrap_1v2_95CI\": [0.6108, 0.6242], \"bootstrap_1v2_995CI_bonferroni\": [0.6078, 0.6273], \"perm_pvalue_1v2\": 0.0001, \"bonferroni_pass\": true, \"top_feature\": \"freq_entropy\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T14:14:41.623Z\"}, \"exp_qwen_cont_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T09:27:38.591Z\", \"updated_at\": \"2026-05-22T14:59:22.490Z\", \"hypothesis\": \"增加 Qwen-cont C4 样本量从 5k→10k 可将 1v2 bootstrap std 缩小 ~√2 倍，使 Bonferroni 99.5% CI lower bound 恢复到 θ=0.60 以上\", \"spec\": {\"command\": \"bash /tmp/run_qwen_cont_10k.sh (Phase1: base generation + Phase2: instruct scoring)\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1 (RTX PRO 6000 Blackwell 96GB)\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_qwen_cont_10k\", \"data_count\": 10000, \"model_name\": \"Qwen/Qwen2.5-1.5B (base, continuation) + Qwen/Qwen2.5-1.5B-Instruct (scorer)\", \"seed\": 42, \"checkpoint_path\": \"results/exp_qwen_cont_10k/\", \"log_path\": \"/tmp/exp_qwen_cont_10k_phase1.log\"}, \"metrics\": {\"K_star\": 2, \"AUC_0v1\": 0.9875, \"AUC_1v2\": 0.6346, \"AUC_2v3\": 0.5616, \"AUC_3v4\": 0.5451, \"AUC_4v5\": 0.5254, \"bootstrap_1v2_95CI\": [0.6282, 0.6409], \"bootstrap_1v2_995CI_bonferroni\": [0.6255, 0.6436], \"perm_pvalue_1v2\": 0.0001, \"bonferroni_pass\": true, \"top_feature\": \"freq_entropy\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T14:47:57.847Z\"}, \"exp_pythia14b_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T11:59:05.554Z\", \"updated_at\": \"2026-05-22T12:00:24.157Z\", \"hypothesis\": \"统一所有 K*=2 configs 样本量至 10K，避免 selective precision boosting 质疑。Pythia-1.4B 5K 已稳定通过 Bonferroni (CI_lower≈0.641>0.60)，10K 为一致性验证。\", \"spec\": {\"command\": \"python3 scripts/run_pipeline.py --model_path pythia-1.4b --num_samples 10000 --max_depth 5 --batch_size 32 --generation_mode continuation + Phase2 Qwen scorer\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:3 (RTX PRO 6000 Blackwell 96GB)\", \"data_path\": \"data/exp_pythia14b_c4_10k\", \"data_count\": 10000, \"model_name\": \"Pythia-1.4B (gen) + Qwen2.5-1.5B-Instruct (scorer)\", \"seed\": 42, \"log_path\": \"N/A\", \"note\": \"重复条目，已合并到 exp_pythia14b_c4_10k\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-22T12:00:24.157Z\"}, \"exp_gemma27b_c4\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-22T07:57:19.726Z\", \"updated_at\": \"2026-05-22T08:11:14.747Z\", \"hypothesis\": \"Gemma-2-27B (27B params, base model) on C4 domain will show slower depth saturation (higher K*) than smaller models due to greater generation capacity, while maintaining the universal depth-dependent distinguishability pattern observed across model families.\"}, \"seed_qwen15b_c4_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T00:34:11.792Z\", \"updated_at\": \"2026-05-22T06:39:21.815Z\", \"hypothesis\": \"Qwen-1.5B C4 的 K*=2 结论在 seed=123 下仍成立（原始 seed=42），验证 OBD 的 depth boundary 不依赖随机种子\", \"spec\": {\"command\": \"run_pipeline.py --generation_mode rewrite --top_p 0.95 --seed 123 (C4)\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"3156\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/seed_qwen15b_c4_s123/\", \"submitted_at\": \"2026-05-22T03:58:27.354Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/seed_robustness/seed_qwen15b_c4_s123\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B-Instruct\", \"seed\": 123, \"metrics\": {\"K_star\": 2, \"auc_0v1\": 0.9956, \"auc_1v2\": 0.7014, \"auc_2v3\": 0.5911, \"auc_3v4\": 0.5405, \"auc_4v5\": 0.5335}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/seed_qwen15b_c4_s123/\", \"wall_clock_seconds\": 9654.5, \"gpu_hours\": 2.68}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T06:39:21.815Z\"}, \"seed_qwen15b_wiki_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T00:34:09.969Z\", \"updated_at\": \"2026-05-22T06:39:19.860Z\", \"hypothesis\": \"Qwen-1.5B WikiText 的 K*=2 结论在 seed=123 下仍成立（原始 seed=42），验证 OBD 的 depth boundary 不依赖随机种子\", \"spec\": {\"command\": \"run_pipeline.py --generation_mode rewrite --top_p 0.95 --seed 123\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"3005\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/seed_qwen15b_wiki_s123/\", \"submitted_at\": \"2026-05-22T03:58:25.151Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/seed_robustness/seed_qwen15b_wiki_s123\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B-Instruct\", \"seed\": 123, \"metrics\": {\"K_star\": 3, \"auc_0v1\": 0.9945, \"auc_1v2\": 0.7059, \"auc_2v3\": 0.6067, \"auc_3v4\": 0.5531, \"auc_4v5\": 0.5292}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/seed_qwen15b_wiki_s123/\", \"wall_clock_seconds\": 9654.7, \"gpu_hours\": 2.68}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-22T06:39:19.860Z\"}, \"seed_pythia14b_wiki_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T00:34:08.091Z\", \"updated_at\": \"2026-05-22T06:39:17.971Z\", \"hypothesis\": \"Pythia-1.4B WikiText 的 K*=2 结论在 seed=123 下仍成立（原始 seed=42），验证 OBD 的 depth boundary 不依赖随机种子\", \"spec\": {\"command\": \"run_pipeline.py --generation_mode continuation --top_p 0.95 --seed 123 (two-phase: Pythia gen + Qwen score)\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"2863\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/seed_pythia14b_wiki_s123/\", \"submitted_at\": \"2026-05-22T03:58:22.018Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/seed_robustness/seed_pythia14b_wiki_s123\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b (generator) + Qwen2.5-1.5B-Instruct (scorer)\", \"seed\": 123, \"metrics\": {\"K_star\": 1, \"auc_0v1\": 0.9751, \"auc_1v2\": 0.5766, \"auc_2v3\": 0.5318, \"auc_3v4\": 0.5175, \"auc_4v5\": 0.527}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/seed_pythia14b_wiki_s123/\", \"wall_clock_seconds\": 9656.0, \"gpu_hours\": 2.68}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T06:39:17.971Z\"}, \"7b-cross-transfer\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:51:00.658Z\", \"updated_at\": \"2026-05-22T00:54:55.385Z\", \"conclusion\": \"killed\"}, \"arxiv_multi_source\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:26:09.176Z\", \"updated_at\": \"2026-05-22T00:54:54.548Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export CUDA_VISIBLE_DEVICES=1 && cd /root/autodl-tmp/gen-depth-contamination && python scripts/run_multi_source_arxiv.py 2>&1 | tee results/exp_multi_source_arxiv/run.log\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"298833\", \"log_path\": \"~/runs/gen-depth-contamination/arxiv_multi_source.log\", \"submitted_at\": \"2026-05-20T08:26:08.709Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r10_nofilter\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:16:37.475Z\", \"updated_at\": \"2026-05-22T00:54:53.730Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && CUDA_VISIBLE_DEVICES=1 python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy no_filter --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"333215\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r10_nofilter.log\", \"submitted_at\": \"2026-05-20T17:16:36.869Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r10_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:16:39.694Z\", \"updated_at\": \"2026-05-22T00:54:52.904Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && CUDA_VISIBLE_DEVICES=2 python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy binary --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"333292\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r10_binary.log\", \"submitted_at\": \"2026-05-20T17:16:39.317Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r10_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:16:41.394Z\", \"updated_at\": \"2026-05-22T00:54:52.064Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && CUDA_VISIBLE_DEVICES=3 python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy graduated --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"333434\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r10_graduated.log\", \"submitted_at\": \"2026-05-20T17:16:40.993Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r30_nofilter\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:16:43.195Z\", \"updated_at\": \"2026-05-22T00:54:44.685Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && CUDA_VISIBLE_DEVICES=0 python scripts/exp_contamination_rate_sweep.py --rate 30 --strategy no_filter --device cuda:0\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"223186\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r30_nofilter.log\", \"submitted_at\": \"2026-05-20T17:16:42.824Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_nofilter\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:34:33.240Z\", \"updated_at\": \"2026-05-22T00:54:43.784Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy no_filter --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_nofilter.log\", \"submitted_at\": \"2026-05-20T17:34:32.842Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:34:35.595Z\", \"updated_at\": \"2026-05-22T00:54:42.896Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy binary --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_binary.log\", \"submitted_at\": \"2026-05-20T17:34:35.217Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:34:37.559Z\", \"updated_at\": \"2026-05-22T00:54:42.034Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy graduated --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_graduated.log\", \"submitted_at\": \"2026-05-20T17:34:37.105Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r30_nofilter\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:34:39.366Z\", \"updated_at\": \"2026-05-22T00:54:41.166Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 30 --strategy no_filter --device cuda:0 --eval_only\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r30_nofilter.log\", \"submitted_at\": \"2026-05-20T17:34:38.989Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_nf\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:35:11.100Z\", \"updated_at\": \"2026-05-22T00:54:40.358Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy no_filter --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"338477\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_nf.log\", \"submitted_at\": \"2026-05-20T17:35:10.713Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_bin\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:35:13.515Z\", \"updated_at\": \"2026-05-22T00:54:39.423Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy binary --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"338554\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_bin.log\", \"submitted_at\": \"2026-05-20T17:35:13.136Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_grad\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:35:15.378Z\", \"updated_at\": \"2026-05-22T00:54:37.930Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy graduated --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"338694\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_grad.log\", \"submitted_at\": \"2026-05-20T17:35:14.990Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r30_nf\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:35:17.531Z\", \"updated_at\": \"2026-05-22T00:54:36.954Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 30 --strategy no_filter --device cuda:0 --eval_only\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"224549\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r30_nf.log\", \"submitted_at\": \"2026-05-20T17:35:17.149Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_eval_r10_nf_v2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:44:37.119Z\", \"updated_at\": \"2026-05-22T00:54:36.068Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 10 --strategy no_filter --device cuda:0 --eval_only\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"341368\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_eval_r10_nf_v2.log\", \"submitted_at\": \"2026-05-20T17:44:36.698Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r30_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:44:38.912Z\", \"updated_at\": \"2026-05-22T00:54:31.052Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 30 --strategy binary --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"341445\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r30_binary.log\", \"submitted_at\": \"2026-05-20T17:44:38.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r30_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:44:40.942Z\", \"updated_at\": \"2026-05-22T00:54:30.235Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 30 --strategy graduated --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"341524\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r30_graduated.log\", \"submitted_at\": \"2026-05-20T17:44:40.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r50_nf\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:46:06.026Z\", \"updated_at\": \"2026-05-22T00:54:29.360Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 50 --strategy no_filter --device cuda:0\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"225683\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r50_nf.log\", \"submitted_at\": \"2026-05-20T17:46:05.636Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r50_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:49:15.968Z\", \"updated_at\": \"2026-05-22T00:54:28.489Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 50 --strategy binary --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"344316\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r50_binary.log\", \"submitted_at\": \"2026-05-20T17:53:07.990Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r50_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:53:10.838Z\", \"updated_at\": \"2026-05-22T00:54:27.679Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 50 --strategy graduated --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"344395\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r50_graduated.log\", \"submitted_at\": \"2026-05-20T17:53:10.443Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r100_nf\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:53:12.678Z\", \"updated_at\": \"2026-05-22T00:54:26.843Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 100 --strategy no_filter --device cuda:0\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"226555\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r100_nf.log\", \"submitted_at\": \"2026-05-20T17:53:12.278Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r100_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:53:46.876Z\", \"updated_at\": \"2026-05-22T00:54:25.989Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://huggingface.co && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 100 --strategy graduated --device cuda:0\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:1\"], \"pid\": \"226991\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r100_graduated.log\", \"submitted_at\": \"2026-05-20T17:53:46.454Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"sweep_r100_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:53:14.587Z\", \"updated_at\": \"2026-05-22T00:54:25.067Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_contamination_rate_sweep.py --rate 100 --strategy binary --device cuda:0\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"227976\", \"log_path\": \"~/runs/gen-depth-contamination/sweep_r100_binary.log\", \"submitted_at\": \"2026-05-20T18:00:00.616Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"deberta_filtering_predict\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:48:51.515Z\", \"updated_at\": \"2026-05-22T00:54:24.104Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && rm -rf /root/autodl-tmp/.hf_cache/models--microsoft--deberta-v3-base/.no_exist && python -c 'from transformers import AutoTokenizer, AutoModelForSequenceClassification; print(\\\\\\\"Downloading deberta-v3-base...\\\\\\\"); AutoTokenizer.from_pretrained(\\\\\\\"microsoft/deberta-v3-base\\\\\\\", cache_dir=\\\\\\\"/root/autodl-tmp/.hf_cache\\\\\\\"); AutoModelForSequenceClassification.from_pretrained(\\\\\\\"microsoft/deberta-v3-base\\\\\\\", num_labels=6, cache_dir=\\\\\\\"/root/autodl-tmp/.hf_cache\\\\\\\"); print(\\\\\\\"Download complete.\\\\\\\")' && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && cd /root/autodl-tmp/gen-depth-contamination && CUDA_VISIBLE_DEVICES=2 python scripts/exp_deberta_filtering_predict.py --device cuda:0\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"349680\", \"log_path\": \"~/runs/gen-depth-contamination/deberta_filtering_predict.log\", \"submitted_at\": \"2026-05-20T18:40:45.030Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"deberta_filter_no_filter\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:11:24.655Z\", \"updated_at\": \"2026-05-22T00:54:23.131Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && export HF_DATASETS_OFFLINE=0 && export HF_HUB_OFFLINE=0 && export TRANSFORMERS_OFFLINE=0 && cd /root/autodl-tmp/gen-depth-contamination && python -u scripts/exp_deberta_filtering_comparison.py --strategy no_filter --device cuda:0 --seed 42\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"353797\", \"log_path\": \"~/runs/gen-depth-contamination/deberta_filter_no_filter.log\", \"submitted_at\": \"2026-05-20T19:12:18.634Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"deberta_filter_obd_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:11:26.462Z\", \"updated_at\": \"2026-05-22T00:54:18.302Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && export HF_DATASETS_OFFLINE=0 && export HF_HUB_OFFLINE=0 && export TRANSFORMERS_OFFLINE=0 && cd /root/autodl-tmp/gen-depth-contamination && python -u scripts/exp_deberta_filtering_comparison.py --strategy obd_binary --device cuda:0 --seed 42\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"353876\", \"log_path\": \"~/runs/gen-depth-contamination/deberta_filter_obd_binary.log\", \"submitted_at\": \"2026-05-20T19:12:21.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"deberta_filter_deberta_binary\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:11:29.363Z\", \"updated_at\": \"2026-05-22T00:54:17.473Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && export HF_DATASETS_OFFLINE=0 && export HF_HUB_OFFLINE=0 && export TRANSFORMERS_OFFLINE=0 && cd /root/autodl-tmp/gen-depth-contamination && python -u scripts/exp_deberta_filtering_comparison.py --strategy deberta_binary --device cuda:0 --seed 42\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"354020\", \"log_path\": \"~/runs/gen-depth-contamination/deberta_filter_deberta_binary.log\", \"submitted_at\": \"2026-05-20T19:12:23.647Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"deberta_filter_deberta_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:26:32.955Z\", \"updated_at\": \"2026-05-22T00:54:16.540Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && export HF_ENDPOINT=https://hf-mirror.com && export HF_HUB_DISABLE_XET=1 && python -u scripts/exp_deberta_filtering_comparison.py --strategy deberta_graduated --device cuda:0 --seed 42\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"359411\", \"log_path\": \"~/runs/gen-depth-contamination/deberta_filter_deberta_graduated.log\", \"submitted_at\": \"2026-05-20T19:28:15.359Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"seed2_no_filter\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T20:20:45.368Z\", \"updated_at\": \"2026-05-22T00:54:15.656Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_DISABLE_XET=1 HF_ENDPOINT=https://hf-mirror.com python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 2 --num_seeds 1 --strategy no_filter --skip_base\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"362953\", \"log_path\": \"~/runs/gen-depth-contamination/seed2_no_filter.log\", \"submitted_at\": \"2026-05-20T20:20:44.951Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"seed2_binary_ours\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T20:20:47.753Z\", \"updated_at\": \"2026-05-22T00:54:14.713Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_DISABLE_XET=1 HF_ENDPOINT=https://hf-mirror.com python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 2 --num_seeds 1 --strategy binary_ours --skip_base\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"363095\", \"log_path\": \"~/runs/gen-depth-contamination/seed2_binary_ours.log\", \"submitted_at\": \"2026-05-20T20:20:47.308Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"seed2_graduated\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T20:20:49.637Z\", \"updated_at\": \"2026-05-22T00:54:13.865Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_DISABLE_XET=1 HF_ENDPOINT=https://hf-mirror.com python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 2 --num_seeds 1 --strategy graduated --skip_base\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"363242\", \"log_path\": \"~/runs/gen-depth-contamination/seed2_graduated.log\", \"submitted_at\": \"2026-05-20T20:20:49.203Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"gsm8k_patch_nf_s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:13:12.767Z\", \"updated_at\": \"2026-05-22T00:54:13.005Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_DISABLE_XET=1 HF_ENDPOINT=https://hf-mirror.com python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 0 --num_seeds 1 --strategy no_filter --skip_base\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"368659\", \"log_path\": \"~/runs/gen-depth-contamination/gsm8k_patch_nf_s0.log\", \"submitted_at\": \"2026-05-20T21:13:12.327Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"gsm8k_patch_bo_s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:13:15.584Z\", \"updated_at\": \"2026-05-22T00:54:12.180Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_DISABLE_XET=1 HF_ENDPOINT=https://hf-mirror.com python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 0 --num_seeds 1 --strategy binary_ours --skip_base\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"368799\", \"log_path\": \"~/runs/gen-depth-contamination/gsm8k_patch_bo_s0.log\", \"submitted_at\": \"2026-05-20T21:13:15.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"gsm8k_patch_grad_s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:13:17.809Z\", \"updated_at\": \"2026-05-22T00:54:11.337Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_DISABLE_XET=1 HF_ENDPOINT=https://hf-mirror.com python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 0 --num_seeds 1 --strategy graduated --skip_base\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"368942\", \"log_path\": \"~/runs/gen-depth-contamination/gsm8k_patch_grad_s0.log\", \"submitted_at\": \"2026-05-20T21:13:17.386Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"gsm8k-serial-rerun\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:59:44.212Z\", \"updated_at\": \"2026-05-22T00:54:10.300Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && export HF_HUB_DISABLE_XET=1 && export HF_ENDPOINT=https://hf-mirror.com && python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 1 --num_seeds 1 --strategy no_filter --skip_base && python scripts/exp_expanded_downstream_eval.py --device cuda:0 --seed_start 1 --num_seeds 1 --strategy binary_ours --skip_base && lm_eval --model hf --model_args pretrained=Qwen/Qwen2.5-1.5B --tasks gsm8k --num_fewshot 5 --batch_size auto --device cuda:0 --output_path results/exp_expanded_downstream_eval/base_gsm8k_eval\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"373073\", \"log_path\": \"~/runs/gen-depth-contamination/gsm8k-serial-rerun.log\", \"submitted_at\": \"2026-05-20T21:59:43.784Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"exp_008_retrain_chain\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T19:26:02.931Z\", \"updated_at\": \"2026-05-22T00:53:20.061Z\", \"hypothesis\": \"Retrain-chain ecological validity: Pythia-1.4B LoRA (rank=16, alpha=32) retrain-chain K* ≤ prompt-chain K*=2. 每代独立 LoRA fine-tune 1 epoch on 前代输出，再用 fine-tuned model 生成下一代。验证 prompt-chain 是 conservative upper bound。C4 5K docs, depth 0-4, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"conclusion\": \"killed\"}, \"exp_olmo_retrain_v2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:36:11.450Z\", \"updated_at\": \"2026-05-22T00:53:19.065Z\", \"hypothesis\": \"OLMo-1B retrain-chain ecological validity (v2, fix M009 model download): LoRA rank=16, alpha=32, 1 epoch per generation on C4 5K docs. Retrain-chain K* ≤ prompt-chain K*=2, confirming prompt-chain as conservative upper bound. Independent LoRA per generation, depth 0-4, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_olmo_retrain_chain\", \"conclusion\": \"killed\", \"notes\": \"Director 决定放弃 OLMo retrain-chain (2026-05-18)。原因：cqa1 两次下载失败（M009 模型权重中断 + 网络端口耗尽），DDL 紧张不再重试。cuda:0 重新分配给 code domain 备用或 Qwen retrain-chain。\"}, \"exp_pythia69b_c4_nuc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T13:57:54.120Z\", \"updated_at\": \"2026-05-21T23:00:07.454Z\", \"hypothesis\": \"Pythia-6.9B 在 C4 上使用 nucleus sampling（非 greedy）的 K*=2，与其他 continuation 模型的 decoding 策略对齐，消除 greedy 高估 confound。生成阶段自评，完成后用 Qwen-1.5B scorer 重跑 features+OBD（方案 2）。\", \"parent\": \"exp_pythia69b_c4_depth_chain_v3\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path ... --scorer_path Qwen2.5-1.5B --num_samples 5000 --max_depth 5 --generation_mode continuation --data_dir data/exp_pythia69b_c4_nuc --results_dir results/exp_pythia69b_c4_nuc\", \"server\": \"cqa1-22115\", \"data_path\": \"data/exp_pythia69b_c4_nuc\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-6.9b\", \"seed\": \"default\", \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A (full pipeline: seed->generation->features->OBD)\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/pythia69b_nuc_v2.log\", \"checkpoint_path\": \"results/exp_pythia69b_c4_nuc_qwen/\"}, \"conclusion\": \"negative\", \"metrics\": {\"K_star\": 1, \"pairwise_auc\": {\"0v1\": 0.9599, \"1v2\": 0.5955, \"2v3\": 0.5298, \"3v4\": 0.5135}, \"scorer\": \"Qwen-1.5B\", \"theta\": 0.6, \"note\": \"1v2 AUC borderline (0.0045 below threshold)\"}, \"completed_at\": \"2026-05-21T23:00:07.454Z\"}, \"exp_pythia69b_c4_depth_chain_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:21:54.364Z\", \"updated_at\": \"2026-05-21T19:55:37.923Z\", \"hypothesis\": \"Pythia-6.9B 在 C4 上的 K*=2，与其他 ≥7B 模型一致，验证 K*=2 不依赖 Qwen 家族。使用 Qwen-1.5B scorer（D095）。\", \"parent\": \"exp_pythia69b_c4_depth_chain_v2\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/models--EleutherAI--pythia-6.9b/snapshots/c0e3eee36dc47af0c49f361c74cfe459c09f7f23 --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --num_samples 5000 --max_depth 5 --batch_size 4 --feat_batch_size 2 --generation_mode continuation --no_sample --data_dir data/exp_pythia69b_c4 --results_dir results/exp_pythia69b_c4\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"395575\", \"log_path\": \"~/runs/gen-depth-contamination/exp_pythia69b_c4_depth_chain_v3.log\", \"submitted_at\": \"2026-05-21T03:22:20.098Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"EleutherAI/pythia-6.9b\", \"model_path\": \"/root/autodl-tmp/.hf_cache/models--EleutherAI--pythia-6.9b/snapshots/c0e3eee36dc47af0c49f361c74cfe459c09f7f23\", \"scorer_path\": \"/root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"data_path\": \"data/exp_pythia69b_c4\", \"data_count\": 5000, \"seed\": \"default\", \"generation_mode\": \"continuation\", \"no_sample\": true, \"max_depth\": 5, \"checkpoint_source\": \"N/A (full pipeline)\", \"eval_data\": \"N/A (full pipeline: seed->generation->features->OBD)\", \"wall_clock_seconds\": 32849.3, \"gpu_hours\": 9.12}, \"reproduce\": {\"finished_at\": \"2026-05-21T12:29:46.273Z\"}, \"failure_reason\": \"greedy confound (--no_sample): AUC_1v2 inflated to 0.8542, not usable for cross-model comparison. K*=2 under greedy is artifact, not genuine nucleus result.\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-21T12:29:49.365Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T12:29:53.480338+00:00\"}]}, \"metrics\": {\"0v1_auc\": 0.9941, \"1v2_auc\": 0.8542, \"2v3_auc\": 0.5373, \"3v4_auc\": 0.5339, \"4v5_auc\": 0.5211, \"kstar_at_060\": 2, \"0v1_jsd\": 0.53459, \"1v2_jsd\": 0.06438, \"2v3_jsd\": 0.00502, \"empty_texts_total\": 144, \"features_rows\": 30000}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_pythia69b_c4/features.csv\", \"log_path\": \"~/runs/gen-depth-contamination/exp_pythia69b_c4_depth_chain_v3.log\"}, \"exp_pythia14b_c4_rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T11:10:50.827Z\", \"updated_at\": \"2026-05-21T14:09:26.792Z\", \"hypothesis\": \"Pythia-1.4B C4 depth chain 可复现性验证：标准化 pipeline（Qwen-1.5B scorer）下 K* 值与主表一致。\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path pythia-1.4b --scorer_path Qwen2.5-1.5B --generation_mode continuation --no_sample --data_dir data/exp_pythia14b_c4_rerun --results_dir results/exp_pythia14b_c4_rerun\", \"server\": \"cqa1-22115\", \"data_path\": \"data/exp_pythia14b_c4_rerun\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b\", \"seed\": \"default\", \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_pythia14b_c4_rerun/features.csv\", \"log_path\": \"N/A\", \"NOTE\": \"GREEDY (--no_sample) — not comparable to main table nucleus results\"}, \"completed_at\": \"2026-05-21T14:09:16.827Z\", \"metrics\": {\"0v1_auc\": 0.9979, \"1v2_auc\": 0.8786, \"2v3_auc\": 0.5399, \"3v4_auc\": 0.5062, \"4v5_auc\": 0.5025, \"kstar_at_060\": 2, \"0v1_jsd\": 0.5844, \"1v2_jsd\": 0.0718, \"NOTE\": \"GREEDY decoding -- inflated AUC, not comparable to main table\"}}, \"exp_olmo1b_c4_rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T11:10:33.358Z\", \"updated_at\": \"2026-05-21T11:11:13.525Z\", \"hypothesis\": \"OLMo-1B C4 depth chain 可复现性验证：标准化 pipeline（Qwen-1.5B scorer）下 K* 值与主表一致。\", \"conclusion\": \"negative\", \"metrics\": {\"0v1_auc\": 0.986, \"1v2_auc\": 0.508, \"2v3_auc\": 0.4973, \"3v4_auc\": 0.5024, \"4v5_auc\": 0.4942, \"kstar_at_060\": 1, \"main_table_1v2\": 0.6145, \"delta\": -0.1065}, \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/models--allenai--OLMo-1B-hf/... --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --no_sample\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"data_path\": \"data/exp_olmo1b_c4_rerun\", \"data_count\": 5000, \"model_name\": \"allenai/OLMo-1B-hf\", \"seed\": \"default\", \"checkpoint_path\": \"results/exp_olmo1b_c4_rerun/\", \"log_path\": \"results/exp_olmo1b_c4_rerun/experiment_config.json\", \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\"}, \"completed_at\": \"2026-05-21T11:11:13.525Z\"}, \"exp_pythia69b_c4_depth_chain_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:23:27.242Z\", \"updated_at\": \"2026-05-21T02:46:08.127Z\", \"hypothesis\": \"Pythia-6.9B 在 C4 上的 K*=2，与其他 ≥7B 模型一致，验证 K*=2 不依赖 Qwen 家族。使用 Qwen-1.5B scorer 以匹配主表（D095）。\", \"parent\": \"exp_pythia69b_c4_depth_chain\", \"spec\": {\"model_name\": \"EleutherAI/pythia-6.9b\", \"model_path\": \"/root/autodl-tmp/.hf_cache/models--EleutherAI--pythia-6.9b/snapshots/c0e3eee36dc47af0c49f361c74cfe459c09f7f23\", \"scorer_path\": \"/root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"data_path\": \"data/exp_pythia69b_c4 (C4 seed from run_pipeline.py)\", \"data_count\": 5000, \"seed\": \"default\", \"generation_mode\": \"continuation\", \"no_sample\": true, \"max_depth\": 5, \"batch_size\": 4, \"feat_batch_size\": 2, \"num_samples\": 5000, \"command\": \"python scripts/run_pipeline.py --model_path .../pythia-6.9b --scorer_path .../Qwen2___5-1___5B --num_samples 5000 --max_depth 5 --generation_mode continuation --no_sample\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"391937\", \"log_path\": \"~/runs/gen-depth-contamination/exp_pythia69b_c4_depth_chain_v2.log\", \"submitted_at\": \"2026-05-21T02:23:38Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"N/A (full pipeline re-run, not eval)\", \"eval_data\": \"N/A (full pipeline: seed→generation→features→OBD)\", \"failure_reason\": \"模型文件不完整: 缺少 model-00001-of-00002.safetensors, v1 下载中断仅完成 66%\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 1350.1, \"gpu_hours\": 0.38}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T02:46:08.127Z\"}, \"exp_pythia69b_c4_depth_chain\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T01:47:28.696Z\", \"updated_at\": \"2026-05-21T02:23:07.638Z\", \"hypothesis\": \"Pythia-6.9B 在 C4 上的 K*=2，与其他 ≥7B 模型一致，验证 K*=2 不依赖 Qwen 家族。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && cd /root/autodl-tmp/gen-depth-contamination && export HF_ENDPOINT=https://hf-mirror.com && export HF_HUB_DISABLE_XET=1 && echo '=== Downloading Pythia-6.9B ===' && python -c 'from huggingface_hub import snapshot_download; path=snapshot_download(\\\\\\\"EleutherAI/pythia-6.9b\\\\\\\", cache_dir=\\\\\\\"/root/autodl-tmp/.hf_cache\\\\\\\"); print(f\\\\\\\"MODEL_PATH={path}\\\\\\\")' && MODEL_PATH=\\\\$(python -c 'from huggingface_hub import snapshot_download; print(snapshot_download(\\\\\\\"EleutherAI/pythia-6.9b\\\\\\\", cache_dir=\\\\\\\"/root/autodl-tmp/.hf_cache\\\\\\\"))') && echo \\\\\\\"=== Running pipeline with model at \\\\$MODEL_PATH ===\\\\\\\" && mkdir -p data/exp_pythia69b_c4 results/exp_pythia69b_c4 && python scripts/run_pipeline.py --model_path \\\\$MODEL_PATH --data_dir data/exp_pythia69b_c4 --results_dir results/exp_pythia69b_c4 --num_samples 5000 --max_depth 5 --batch_size 4 --feat_batch_size 2 --generation_mode continuation --no_sample\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"390600\", \"log_path\": \"~/runs/gen-depth-contamination/exp_pythia69b_c4_depth_chain.log\", \"submitted_at\": \"2026-05-21T01:56:36.394Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"D095 violation: missing --scorer_path, used self-scoring instead of Qwen-1.5B. Killed by Director. Will resubmit as v2.\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 1591.2, \"gpu_hours\": 0.44}, \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-21T01:54:27.864Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && cd /root/autodl-tmp/gen-depth-contamination && export HF_ENDPOINT=https://hf-mirror.com && export HF_HUB_DISABLE_XET=1 && echo '=== Downloading Pythia-6.9B ===' && python -c 'from huggingface_hub import snapshot_download; path=snapshot_download(\\\\\\\"EleutherAI/pythia-6.9b\\\\\\\", cache_dir=\\\\\\\"/root/autodl-tmp/.hf_cache\\\\\\\"); print(f\\\\\\\"MODEL_PATH={path}\\\\\\\")' && MODEL_PATH=\\\\$(python -c 'from huggingface_hub import snapshot_download; print(snapshot_download(\\\\\\\"EleutherAI/pythia-6.9b\\\\\\\", cache_dir=\\\\\\\"/root/autodl-tmp/.hf_cache\\\\\\\"))') && echo \\\\\\\"=== Running pipeline with model at \\\\$MODEL_PATH ===\\\\\\\" && mkdir -p data/exp_pythia69b_c4 results/exp_pythia69b_c4 && python scripts/run_pipeline.py --model_path \\\\$MODEL_PATH --data_dir data/exp_pythia69b_c4 --results_dir results/exp_pythia69b_c4 --num_samples 5000 --max_depth 5 --batch_size 4 --feat_batch_size 2 --generation_mode continuation --no_sample\\\"\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\"}, \"pid\": \"390600\", \"log_path\": \"~/runs/gen-depth-contamination/exp_pythia69b_c4_depth_chain.log\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T02:23:07.638Z\"}, \"exp_expanded_downstream_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:02:47.262Z\", \"updated_at\": \"2026-05-21T00:23:17.997Z\", \"hypothesis\": \"K*-guided binary filtering consistently outperforms graduated filtering across a broader set of benchmarks (GSM8K, ARC-Challenge, WinoGrande, TruthfulQA, PIQA), not just MMLU/HellaSwag, validating the generalizability of the filtering consistency claim in Section 5.\", \"spec\": {\"command\": \"python scripts/run_expanded_eval.py (base eval + 3 strategies × 3 seeds LoRA train+eval, 5 benchmarks)\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"pid\": \"334626\", \"log_path\": \"cqa1-22115:/root/gen-depth-contamination/results/exp_expanded_downstream_eval/\", \"submitted_at\": \"2026-05-20T17:17:37.434Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/\", \"data_count\": 30000, \"model_name\": \"Qwen2.5-1.5B\", \"seed\": \"42,123,456\", \"benchmarks\": \"PIQA, TruthfulQA-MC2, WinoGrande, ARC-Challenge, GSM8K\", \"checkpoint_path\": \"cqa1-22115:/root/gen-depth-contamination/results/exp_expanded_downstream_eval/\", \"wall_clock_seconds\": 24379.3, \"gpu_hours\": 6.77}, \"gpus\": [], \"metrics\": {\"metric_standard\": \"PIQA=acc_norm, ARC-C=acc_norm, WinoGrande=acc, TruthfulQA=mc2, GSM8K=exact_match(strict)\", \"base_model\": {\"piqa\": 0.7612, \"arc_c\": 0.5486, \"winogrande\": 0.6456, \"truthfulqa\": 0.4659, \"gsm8k\": 0.6224}, \"no_filter_mean\": {\"piqa\": 0.7519, \"arc_c\": 0.5193, \"winogrande\": 0.6485, \"truthfulqa\": 0.4246, \"gsm8k\": 0.5666}, \"binary_ours_mean\": {\"piqa\": 0.7479, \"arc_c\": 0.5171, \"winogrande\": 0.6406, \"truthfulqa\": 0.4398, \"gsm8k\": 0.5858}, \"graduated_mean\": {\"piqa\": 0.751, \"arc_c\": 0.519, \"winogrande\": 0.6461, \"truthfulqa\": 0.4245, \"gsm8k\": 0.5613}, \"binary_vs_nf_delta\": {\"piqa\": -0.4, \"arc_c\": -0.22, \"winogrande\": -0.79, \"truthfulqa\": 1.52, \"gsm8k\": 1.92}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:03:56.750Z\"}, \"exp_deberta_filtering_comparison\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:02:50.271Z\", \"updated_at\": \"2026-05-20T20:08:32.368Z\", \"hypothesis\": \"DeBERTa's higher K* on arXiv (K*=4 vs 15D K*=3) does not yield significantly better downstream performance when used for filtering, validating that the 15D lower bound is practically sufficient.\", \"spec\": {\"command\": \"python scripts/exp_deberta_filtering_comparison.py --strategy {no_filter,obd_binary,deberta_binary,deberta_graduated} --device cuda:0 --seed 42\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_024_arxiv/\", \"data_count\": 13200, \"model_name\": \"Qwen/Qwen2.5-1.5B\", \"seed\": 42, \"strategies\": [\"no_filter\", \"obd_binary\", \"deberta_binary\", \"deberta_graduated\"], \"prediction_results\": {\"deberta_accuracy\": 0.5363, \"obd_accuracy\": 0.4741, \"deberta_pred_distribution\": [2184, 1645, 2111, 1971, 1074, 4215], \"obd_pred_distribution\": [2177, 2470, 2196, 1900, 2098, 2359]}, \"lora_config\": {\"rank\": 16, \"alpha\": 32, \"targets\": [\"q_proj\", \"v_proj\"], \"dropout\": 0.05}, \"training_config\": {\"lr\": 0.0002, \"batch_size\": 4, \"grad_accum\": 4, \"epochs\": 1, \"max_length\": 256}, \"gpu_allocation\": {\"no_filter\": \"cuda:1\", \"obd_binary\": \"cuda:2\", \"deberta_binary\": \"cuda:3\", \"deberta_graduated\": \"pending\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_filtering_comparison/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_filtering_comparison/\"}, \"metrics\": {\"no_filter\": {\"mmlu\": 0.5895, \"hellaswag\": 0.6591, \"arc_c\": 0.4352}, \"obd_binary\": {\"mmlu\": 0.588, \"hellaswag\": 0.6599, \"arc_c\": 0.4522}, \"deberta_binary\": {\"mmlu\": 0.587, \"hellaswag\": 0.6593, \"arc_c\": 0.4471}, \"deberta_graduated\": {\"mmlu\": 0.5884, \"hellaswag\": 0.6586, \"arc_c\": 0.442}, \"summary\": \"obd_binary (15D) >= deberta_binary on all 3 benchmarks. DeBERTa K*=4 does not yield better filtering than 15D K*=3. Graduated < binary for both OBD and DeBERTa.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T20:06:51.128Z\"}, \"exp_contamination_rate_sweep\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:02:48.807Z\", \"updated_at\": \"2026-05-20T18:02:19.878Z\", \"hypothesis\": \"Binary filtering (remove depth>=1) consistently outperforms graduated filtering across contamination rates (10/30/50/100%), validating that K*=2 provides actionable curation guidance across realistic contamination scenarios, not just at full contamination.\", \"spec\": {\"command\": \"python scripts/contamination_rate_sweep.py (4 rates x 3 strategies = 12 runs)\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1,cuda:2,cuda:3\", \"pid\": \"333220,333297,333439\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/contamination_sweep/\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B\", \"seed\": 42, \"training_config\": \"LoRA rank=16 alpha=32 1epoch\", \"current_round\": \"rate=10% (no_filter:cuda1/binary:cuda2/graduated:cuda3)\", \"remaining_rounds\": \"rate=30%,50%,100%\", \"eval_benchmarks\": \"MMLU-5shot HellaSwag-10shot ARC-Challenge-25shot\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_contamination_rate_sweep/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_contamination_rate_sweep/summary.json\"}, \"metrics\": {\"rate_10\": {\"no_filter\": {\"mmlu\": 0.5878, \"hellaswag\": 0.6652, \"arc_c\": 0.4471}, \"binary\": {\"mmlu\": 0.5868, \"hellaswag\": 0.6709, \"arc_c\": 0.4462}, \"graduated\": {\"mmlu\": 0.5873, \"hellaswag\": 0.6672, \"arc_c\": 0.4428}}, \"rate_30\": {\"no_filter\": {\"mmlu\": 0.5885, \"hellaswag\": 0.6625, \"arc_c\": 0.4334}, \"binary\": {\"mmlu\": 0.5867, \"hellaswag\": 0.6702, \"arc_c\": 0.448}, \"graduated\": {\"mmlu\": 0.5873, \"hellaswag\": 0.664, \"arc_c\": 0.4334}}, \"rate_50\": {\"no_filter\": {\"mmlu\": 0.5858, \"hellaswag\": 0.6582, \"arc_c\": 0.43}, \"binary\": {\"mmlu\": 0.5913, \"hellaswag\": 0.67, \"arc_c\": 0.4505}, \"graduated\": {\"mmlu\": 0.5848, \"hellaswag\": 0.6606, \"arc_c\": 0.4292}}, \"rate_100\": {\"no_filter\": {\"mmlu\": 0.5707, \"hellaswag\": 0.6217, \"arc_c\": 0.3891}, \"binary\": null, \"graduated\": {\"mmlu\": 0.5701, \"hellaswag\": 0.6215, \"arc_c\": 0.3933}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T18:02:19.878Z\"}, \"exp_olmo_retrain_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:47:22.000Z\", \"updated_at\": \"2026-05-20T14:57:53.008Z\", \"hypothesis\": \"OLMo-1B retrain-chain K*>=4 (matching Pythia/Qwen retrain-chain), confirming retrain-chain K* is protocol-determined not architecture-determined. LoRA rank=16, alpha=32, 1 epoch per generation, C4 5K docs, depth 0-4.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python exp_olmo_retrain_v3.py --device cuda:0\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/olmo_retrain_chain\", \"data_count\": 5000, \"model_name\": \"allenai/OLMo-1B-hf\", \"seed\": 42}, \"metrics\": {\"k_star\": 4, \"pairwise_auc\": {\"0v1\": 0.9873, \"1v2\": 0.8889, \"2v3\": 0.7036, \"3v4\": 0.6817}, \"bootstrap_ci_10k\": {\"0v1\": {\"mean\": 0.9972, \"ci_95\": [0.9967, 0.9977]}, \"1v2\": {\"mean\": 0.9572, \"ci_95\": [0.9542, 0.9601]}, \"2v3\": {\"mean\": 0.8885, \"ci_95\": [0.8814, 0.8947]}, \"3v4\": {\"mean\": 0.8772, \"ci_95\": [0.8684, 0.8852]}}, \"permutation_test\": {\"0v1\": {\"auc\": 0.9988, \"p\": 0}, \"1v2\": {\"auc\": 0.961, \"p\": 0}, \"2v3\": {\"auc\": 0.8919, \"p\": 0.998}, \"3v4\": {\"auc\": 0.8762, \"p\": 1}}}, \"conclusion\": \"success\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/olmo_retrain_v3.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data/olmo_retrain_chain\", \"completed_at\": \"2026-05-20T14:57:53.008Z\"}, \"exp_7b_scorer_arxiv\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T12:33:38.614Z\", \"updated_at\": \"2026-05-20T13:27:43.350Z\", \"hypothesis\": \"Qwen2.5-7B scorer yields same K*=3 as Qwen2.5-1.5B scorer on arXiv depth chains, confirming K* is robust to scorer scale across domains (C4 + arXiv).\", \"parent\": \"exp_024_arxiv_domain\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python /root/autodl-tmp/gen-depth-contamination/scripts/run_7b_scorer_arxiv.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_025_pythia_arxiv + /root/autodl-tmp/gen-depth-contamination/data/exp_arXiv_olmo\", \"data_count\": 26400, \"model_name\": \"Qwen2.5-7B + Qwen2.5-1.5B-Instruct (scorers), Pythia-1.4B + OLMo-1B (generators)\", \"seed\": 42, \"checkpoint_source\": \"pretrained (Qwen2.5-7B, Qwen2.5-1.5B-Instruct)\", \"eval_data\": \"arXiv depth chains (Pythia-1.4B + OLMo-1B, depth 0-5, 2200 samples/depth)\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T13:24:06.236Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T13:24:08.238Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T13:24:11.891882+00:00\"}]}, \"metrics\": {\"pythia_arxiv_qwen1b5\": {\"k_star\": 3, \"0v1\": 0.9872, \"1v2\": 0.7938, \"2v3\": 0.6544}, \"olmo_arxiv_qwen1b5\": {\"k_star\": 1, \"0v1\": 0.9954, \"1v2\": 0.5182, \"2v3\": 0.4956}, \"pythia_arxiv_qwen7b\": {\"k_star\": 3, \"0v1\": 0.9844, \"1v2\": 0.7987, \"2v3\": 0.6551}, \"olmo_arxiv_qwen7b\": {\"k_star\": 1, \"0v1\": 0.9941, \"1v2\": 0.5089, \"2v3\": 0.492}, \"summary\": \"7B scorer and 1.5B scorer yield identical K* on arXiv: Pythia=3, OLMo=1. K* robust to 4.7x scorer scale increase across both C4 and arXiv domains.\"}}, \"exp_014_naturalistic\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:19:56.644Z\", \"updated_at\": \"2026-05-20T13:12:42.795Z\", \"hypothesis\": \"OBD depth predictions on real-world Common Crawl text correlate with independent text quality metrics (vocabulary richness), validating that the depth signal captures meaningful text degradation beyond the synthetic training distribution.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python /root/autodl-tmp/gen-depth-contamination/scripts/run_naturalistic_validation.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp016_qwen_base/features.csv\", \"data_count\": 5000, \"model_name\": \"Qwen/Qwen2.5-1.5B\", \"seed\": 42, \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp014_naturalistic/\"}, \"conclusion\": \"success\", \"metrics\": {\"binary_auc\": 0.9919, \"cc_depth0_ratio\": 0.89, \"freq_entropy_rho\": -0.78, \"ttr_rho\": 0.17, \"note\": \"TTR rho=+0.17 contradicts hypothesis (expected negative). Paper should only report freq_entropy and CC classification, not TTR (or explicitly flag anomalous direction).\"}, \"completed_at\": \"2026-05-20T13:12:42.795Z\"}, \"exp_code_multi_source\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:30:38.921Z\", \"updated_at\": \"2026-05-20T13:12:41.350Z\", \"hypothesis\": \"Code domain multi-source OBD K* preserves single-source ceiling K*=2 when mixing 3 generators (Qwen-7B, LLaMA-8B, Mistral-7B) with unified Qwen2.5-1.5B scorer.\", \"spec\": {\"command\": \"python /root/autodl-tmp/gen-depth-contamination/scripts/run_multi_source_code.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_code_{qwen7b,llama8b,mistral7b}\", \"data_count\": 99000, \"model_name\": \"Qwen2.5-1.5B (scorer)\", \"seed\": 42, \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/data/code_multi_source/\"}, \"metrics\": {\"k_star\": 2, \"generators\": [\"qwen7b\", \"llama8b\", \"mistral7b\"], \"unified_scorer\": \"qwen2.5-1.5b\", \"vocab_only_no_label\": {\"0v1\": 0.7891, \"1v2\": 0.6353, \"2v3\": 0.5121, \"kstar\": 2}, \"vocab_only_with_label\": {\"0v1\": 0.79, \"1v2\": 0.644, \"2v3\": 0.5118, \"kstar\": 2}, \"unified_no_label\": {\"0v1\": 0.9123, \"1v2\": 0.6702, \"2v3\": 0.5013, \"kstar\": 2}, \"unified_with_label\": {\"0v1\": 0.9123, \"1v2\": 0.6803, \"2v3\": 0.5055, \"kstar\": 2}, \"elapsed_seconds\": 2025, \"note\": \"Code multi-source K*=2 matches single-source ceiling across all 4 settings.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T13:12:41.350Z\"}, \"exp_wiki_multi_source\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:31:50.277Z\", \"updated_at\": \"2026-05-20T13:12:39.770Z\", \"hypothesis\": \"Wiki domain multi-source OBD K* preserves single-source ceiling when mixing 3 generators (Qwen1.5B, LLaMA-8B, Mistral-7B) with unified Qwen2.5-1.5B scorer, consistent with C4 multi-source K*=2 and arXiv multi-source K*=3.\", \"spec\": {\"command\": \"python /root/autodl-tmp/gen-depth-contamination/scripts/run_multi_source_wiki.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki,exp_wiki_llama8b,exp_wiki_mistral7b\", \"data_count\": 90000, \"model_name\": \"Qwen2.5-1.5B (scorer)\", \"seed\": 42, \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/data/wiki_multi_source/\"}, \"metrics\": {\"k_star\": 1, \"generators\": [\"qwen1b5\", \"llama8b\", \"mistral7b\"], \"docs_per_generator\": 1000, \"total_rows\": 18000, \"unified_scorer\": \"qwen2.5-1.5b\", \"vocab_only_no_label\": {\"0v1\": 0.7616, \"1v2\": 0.5434, \"2v3\": 0.517, \"kstar\": 1}, \"vocab_only_with_label\": {\"0v1\": 0.7779, \"1v2\": 0.552, \"2v3\": 0.5248, \"kstar\": 1}, \"unified_no_label\": {\"0v1\": 0.9603, \"1v2\": 0.5685, \"2v3\": 0.519, \"kstar\": 1}, \"unified_with_label\": {\"0v1\": 0.9685, \"1v2\": 0.579, \"2v3\": 0.5299, \"kstar\": 1}, \"elapsed_seconds\": 3499, \"note\": \"All 3 generators (qwen1b5/llama8b/mistral7b) participated. K*=1 consistent with cross-scorer single-source results (llama8b K*=1, mistral7b K*=1, qwen K*=2). Mixed pool pulled to K*=1 by majority.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T13:12:39.770Z\"}, \"exp_7b_scorer_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:37:17.489Z\", \"updated_at\": \"2026-05-20T12:53:09.873Z\", \"hypothesis\": \"Qwen2.5-7B scorer yields same K* as Qwen2.5-1.5B scorer on C4 Pythia-1.4B and OLMo-1B depth chains, confirming K* is robust to scorer scale (4.7x parameter increase).\", \"parent\": \"exp_022_cross_scorer\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTORCH_CUDA_ALLOC_CONF=expandable_segments:True CUDA_VISIBLE_DEVICES=0 python /root/autodl-tmp/gen-depth-contamination/scripts/run_7b_scorer_ablation.py'\", \"server\": \"cqa1-22115\", \"data_path\": \"data_exp020_pythia_greedy + data/olmo_c4_cont\", \"data_count\": 60000, \"model_name\": \"Qwen2.5-7B + Qwen2.5-1.5B-Instruct (scorers)\", \"seed\": 42, \"checkpoint_source\": \"exp_022_cross_scorer (Pythia C4 + OLMo C4 depth chain data)\", \"eval_data\": \"C4 depth 0-5 from Pythia-1.4B and OLMo-1B generators\"}, \"metrics\": {\"pythia_c4__qwen1.5b\": {\"k_star\": 2, \"1v2_auc\": 0.8928, \"1v2_ci\": [0.8865, 0.8989]}, \"olmo_c4__qwen1.5b\": {\"k_star\": 1, \"1v2_auc\": 0.4977, \"1v2_ci\": [0.4865, 0.509]}, \"pythia_c4__qwen7b\": {\"k_star\": 2, \"1v2_auc\": 0.8943, \"1v2_ci\": [0.8881, 0.9005]}, \"olmo_c4__qwen7b\": {\"k_star\": 1, \"1v2_auc\": 0.4965, \"1v2_ci\": [0.485, 0.5078]}, \"match\": \"pythia K*(1.5B)=2 == K*(7B)=2; olmo K*(1.5B)=1 == K*(7B)=1\"}, \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp_7b_scorer_ablation.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_7b_scorer_ablation/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T12:53:09.873Z\"}, \"exp_bootstrap_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:51:15.538Z\", \"updated_at\": \"2026-05-20T11:57:24.167Z\", \"hypothesis\": \"10K bootstrap resamples yield tighter CI but no K* verdict flips for borderline Table 2 configurations (LLaMA-8B, Gemma-2-2B, Mistral-7B, 512-tok), confirming robustness of K* assignments at 1K resamples.\", \"spec\": {\"command\": \"python /root/autodl-tmp/gen-depth-contamination/scripts/run_bootstrap_10k.py\", \"server\": \"cqa1-22115\", \"data_path\": \"multiple (exp_018, exp_gemma2b, exp_019, exp_021_512)\", \"data_count\": 40000, \"model_name\": \"LightGBM (CPU-only bootstrap)\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_bootstrap_10k/bootstrap_10k_comparison.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_bootstrap_10k_log.txt\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T11:56:15.385Z\", \"metrics\": {\"configs_tested\": 4, \"configs_missing\": 2, \"results\": {\"llama8b\": {\"auc\": 0.6075, \"ci_1k\": [0.597, 0.617], \"ci_10k\": [0.598, 0.617], \"verdict_1k\": \"BORDERLINE\", \"verdict_10k\": \"BORDERLINE\", \"flipped\": false}, \"gemma2b\": {\"auc\": 0.5981, \"ci_1k\": [0.588, 0.608], \"ci_10k\": [0.588, 0.608], \"verdict_1k\": \"BORDERLINE\", \"verdict_10k\": \"BORDERLINE\", \"flipped\": false}, \"mistral7b\": {\"auc\": 0.5902, \"ci_1k\": [0.58, 0.6], \"ci_10k\": [0.58, 0.6], \"verdict_1k\": \"K*=1\", \"verdict_10k\": \"BORDERLINE\", \"flipped_technical\": true, \"note\": \"CI upper 0.6000→0.6001 (noise, +0.01pp). Point estimate 0.5902 << theta. K*=1 unchanged.\"}, \"512tok\": {\"auc\": 0.6136, \"ci_1k\": [0.604, 0.623], \"ci_10k\": [0.604, 0.623], \"verdict_1k\": \"K*=2\", \"verdict_10k\": \"K*=2\", \"flipped\": false}}, \"missing\": [\"exp_017_qwen_cont (features.csv not on disk)\", \"exp_002_olmo (features.csv not on disk)\"], \"conclusion\": \"No substantive K* flips. 10K CI ~3% tighter. 1K resamples confirmed robust.\"}}, \"exp-014\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:28:44.076Z\", \"updated_at\": \"2026-05-20T11:36:17.784Z\", \"spec\": {\"command\": \"python run_naturalistic_validation.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp016_qwen_base/features.csv\", \"data_count\": 30000, \"model_name\": \"Qwen2.5-1.5B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_014_naturalistic/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_014_naturalistic/naturalistic_validation_results.json\"}, \"conclusion\": \"success\", \"hypothesis\": \"OBD depth classifiers trained on synthetic generation-chain data will assign low depth (d0) to most real Common Crawl texts, and predicted AI probability will correlate negatively with vocabulary richness metrics (freq_entropy, TTR), confirming that the 15D feature space captures genuine human-vs-synthetic distributional differences rather than overfitting to synthetic artifacts.\", \"completed_at\": \"2026-05-20T11:29:09.930Z\", \"metrics\": {\"superseded_by\": \"exp_014_naturalistic\", \"note\": \"Stale duplicate. All metrics and results are in exp_014_naturalistic.\"}}, \"exp_gemma2b_depth\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T06:20:08.546Z\", \"updated_at\": \"2026-05-20T10:07:22.035Z\", \"hypothesis\": \"Gemma-2-2B (6th architecture family) yields K*=2 on C4 web text under continuation mode, consistent with domain ceiling K*=2 observed across 5 other families (Qwen/Pythia/OLMo/LLaMA/Mistral), strengthening the claim that C4 ceiling is architecture-independent.\", \"spec\": {\"command\": \"python /root/autodl-tmp/gen-depth-contamination/scripts/run_gemma2b_depth.py\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": 289968, \"log_path\": \"~/runs/gen-depth-contamination/exp_gemma2b_depth.log\", \"submitted_at\": \"2026-05-20T06:34:42.871Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_id\": \"cuda:0\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/c4_5k\", \"data_count\": 5000, \"model_name\": \"google/gemma-2-2b\", \"seed\": 42, \"wall_clock_seconds\": 11141.9, \"gpu_hours\": 3.09}, \"reproduce\": {\"finished_at\": \"2026-05-20T09:38:23.991Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T09:38:28.803849+00:00\"}]}, \"metrics\": {\"k_star\": 1, \"pairwise_auc\": {\"0v1\": 0.9534, \"1v2\": 0.5981, \"2v3\": 0.5342, \"3v4\": 0.503, \"4v5\": 0.5026}, \"pairwise_auc_std\": {\"0v1\": 0.003, \"1v2\": 0.008, \"2v3\": 0.013, \"3v4\": 0.003, \"4v5\": 0.013}, \"bootstrap_ci_1v2\": {\"ci_lower\": 0.5882, \"ci_upper\": 0.6076}, \"jsd\": {\"0v1\": 0.09882, \"1v2\": 0.008852, \"2v3\": 0.004904, \"3v4\": 0.003742, \"4v5\": 0.003167}, \"ordinal_mae\": 1.3152, \"ordinal_accuracy\": 0.3321, \"note\": \"K*=1, NOT borderline K*=2. 1v2 AUC=0.5981 < theta=0.60. CI upper=0.6076 crosses theta but point estimate below.\"}, \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_gemma2b_depth/summary.txt\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_gemma2b_depth/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T09:40:24.773Z\"}, \"exp_deberta_code_qwen1b5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:34:21.140Z\", \"updated_at\": \"2026-05-20T09:43:22.944Z\", \"hypothesis\": \"DeBERTa supervised classifier on Code domain yields K*=2 (matching OBD K*=2), confirming representation-independent domain ceiling holds for Code domain (C4 K*=2, wiki K*=3, arXiv K*=3, code K*=2).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 HF_HOME=/root/autodl-tmp/.hf_cache PYTORCH_CUDA_ALLOC_CONF=expandable_segments:True python /root/autodl-tmp/gen-depth-contamination/scripts/run_deberta_code.py\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"294849\", \"log_path\": \"~/runs/gen-depth-contamination/exp_deberta_code_qwen1b5.log\", \"submitted_at\": \"2026-05-20T07:33:30.520Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7792.4, \"gpu_hours\": 2.16}, \"reproduce\": {\"finished_at\": \"2026-05-20T09:20:38.702Z\"}, \"metrics\": {\"K_star\": 2, \"theta\": 0.6, \"auc_0v1\": 1, \"auc_1v2\": 0.8076, \"auc_2v3\": 0.5933, \"auc_3v4\": 0.5492, \"auc_4v5\": 0.5311, \"ci_0v1\": [0.9999, 1], \"ci_1v2\": [0.8001, 0.8147], \"ci_2v3\": [0.5847, 0.6018], \"ci_3v4\": [0.541, 0.5573], \"ci_4v5\": [0.5235, 0.5388], \"obd_auc_0v1\": 0.9388, \"obd_auc_1v2\": 0.7382, \"obd_auc_2v3\": 0.53, \"obd_auc_3v4\": 0.5022, \"obd_auc_4v5\": 0.5219, \"elapsed_seconds\": 5780}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_code_qwen1b5/code_qwen1b5.json\", \"log_path\": \"~/runs/gen-depth-contamination/exp_deberta_code_qwen1b5.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T09:43:22.944Z\"}, \"exp_multi_source_arxiv\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:46:18.107Z\", \"updated_at\": \"2026-05-20T08:47:00.705Z\", \"hypothesis\": \"Multi-source OBD K* on arXiv domain preserves domain ceiling K*=3 when mixing 3 generators (Qwen/Pythia/LLaMA-8B) with unified Qwen2.5-1.5B scorer, consistent with single-source arXiv K*=3 and higher than C4 multi-source K*=2, confirming domain hierarchy in multi-source setting.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python scripts/run_multi_source_arxiv.py\", \"server\": \"cqa1-22115\", \"data_path\": \"data/exp_024_arxiv + data/exp_025_pythia_arxiv + data/exp_arXiv_llama8b\", \"data_count\": 19800, \"model_name\": \"OBD-LightGBM-15D\", \"seed\": 42, \"checkpoint_path\": \"results/exp_multi_source_arxiv/\", \"log_path\": \"results/exp_multi_source_arxiv/summary.json\"}, \"completed_at\": \"2026-05-20T08:46:51.345Z\", \"metrics\": {\"domain\": \"arxiv\", \"generators\": [\"qwen1b5\", \"pythia1b4\", \"llama8b\"], \"unified_scorer\": \"qwen2.5-1.5b\", \"docs_per_generator\": 1000, \"vocab_only_no_label_0v1\": 0.9431, \"vocab_only_no_label_1v2\": 0.6922, \"vocab_only_no_label_2v3\": 0.589, \"vocab_only_no_label_kstar\": 2, \"vocab_only_with_label_0v1\": 0.9436, \"vocab_only_with_label_1v2\": 0.702, \"vocab_only_with_label_2v3\": 0.5883, \"vocab_only_with_label_kstar\": 2, \"unified_no_label_0v1\": 0.9899, \"unified_no_label_1v2\": 0.8117, \"unified_no_label_2v3\": 0.6247, \"unified_no_label_3v4\": 0.5269, \"unified_no_label_kstar\": 3, \"unified_with_label_0v1\": 0.9911, \"unified_with_label_1v2\": 0.8338, \"unified_with_label_2v3\": 0.6276, \"unified_with_label_2v3_ci\": [0.615, 0.6401], \"unified_with_label_3v4\": 0.533, \"unified_with_label_kstar\": 3}}, \"exp_multi_source_detection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T06:20:10.182Z\", \"updated_at\": \"2026-05-20T08:00:14.527Z\", \"hypothesis\": \"OBD K* is preserved when training on a mixed pool of outputs from 3 different generators (Qwen-1.5B, Pythia-1.4B, OLMo-1B), and adding generator identity as an extra feature does not improve depth discrimination.\", \"spec\": {\"command\": \"python scripts/run_multi_source.py\", \"server\": \"cqa1-22115\", \"data_path\": \"data_exp016_qwen_base + data_exp020_pythia_greedy + data/olmo_c4_cont\", \"data_count\": 18000, \"model_name\": \"OBD-LightGBM-15D\", \"seed\": 42, \"checkpoint_path\": \"results/exp_multi_source_detection/\", \"log_path\": \"/tmp/multi_source.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T07:01:21.517Z\", \"metrics\": {\"v2_generators\": [\"qwen1b5\", \"pythia1b4\", \"llama8b\"], \"v2_kstar_no_label\": 2, \"v2_kstar_with_label\": 2, \"v2_0v1_auc_no_label\": 0.968, \"v2_0v1_auc_with_label\": 0.9785, \"v2_1v2_auc_no_label\": 0.7144, \"v2_1v2_auc_with_label\": 0.7251, \"v2_2v3_auc_no_label\": 0.5321, \"v2_2v3_auc_with_label\": 0.5362, \"vocab_only_v1_0v1\": 0.8675, \"vocab_only_v1_1v2\": 0.676, \"vocab_only_v1_2v3\": 0.4938, \"vocab_only_v1_kstar\": 2, \"vocab_only_v2_0v1\": 0.8296, \"vocab_only_v2_1v2\": 0.683, \"vocab_only_v2_2v3\": 0.5057, \"vocab_only_v2_kstar\": 2, \"vocab_only_features\": [\"ttr\", \"hapax_ratio\", \"self_bleu\", \"freq_kurtosis\", \"freq_entropy\", \"low_freq_ratio\"], \"scorer_confound_affects_kstar\": false, \"unified_scorer\": \"qwen2.5-1.5b\", \"unified_no_label_0v1\": 0.9663, \"unified_no_label_1v2\": 0.7105, \"unified_no_label_2v3\": 0.519, \"unified_no_label_kstar\": 2, \"unified_with_label_0v1\": 0.9769, \"unified_with_label_1v2\": 0.7183, \"unified_with_label_2v3\": 0.5165, \"unified_with_label_kstar\": 2, \"unified_single_qwen_kstar\": 2, \"unified_single_pythia_kstar\": 2, \"unified_single_llama8b_kstar\": 1, \"unified_single_qwen_1v2\": 0.6306, \"unified_single_pythia_1v2\": 0.8806, \"unified_single_llama8b_1v2\": 0.6077}}, \"exp_changepoint_kstar\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T06:20:11.788Z\", \"updated_at\": \"2026-05-20T07:21:14.637Z\", \"hypothesis\": \"Non-parametric changepoint detection (PELT) on pairwise AUC sequences should recover K* consistent with the fixed θ=0.60 threshold, validating that K* is not an artifact of threshold choice.\", \"spec\": {\"command\": \"python scripts/run_changepoint_kstar.py\", \"server\": \"cqa1-22115\", \"data_path\": \"results/*/pairwise_auc.json\", \"data_count\": 37, \"model_name\": \"ruptures-PELT\", \"seed\": 42, \"checkpoint_path\": \"results/exp_changepoint_kstar/\", \"log_path\": \"/tmp/changepoint_run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"exact_agreement\": 0.459, \"exact_agreement_n\": \"17/37\", \"within_1_agreement\": 0.946, \"within_1_agreement_n\": \"35/37\", \"cp_direction\": \"always_conservative\", \"disagreement_auc_range\": [0.607, 0.654], \"best_penalty\": 0.1, \"methods_tested\": [\"PELT\", \"BinSeg\", \"BottomUp\"], \"bootstrap_samples\": 2000}, \"completed_at\": \"2026-05-20T07:19:41.765Z\"}, \"exp_cross_transfer_llama8b_to_qwen7b_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:01:09.441Z\", \"updated_at\": \"2026-05-20T05:28:46.650Z\", \"spec\": {\"command\": \"python scripts/run_deberta_cross_transfer.py --train_model wiki_llama8b --test_model wiki_qwen7b --gpu 0\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"275361\", \"log_path\": \"~/runs/gen-depth-contamination/exp_cross_transfer_llama8b_to_qwen7b_v2.log\", \"submitted_at\": \"2026-05-20T03:01:08.673Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/wiki_llama8b/ + wiki_qwen7b/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42, \"checkpoint_source\": \"trained from scratch (cross-transfer rerun of crashed v1)\", \"eval_data\": \"wiki_qwen7b depth 0-5, 20000 samples\", \"checkpoint_path\": \"N/A (OOF predictions only)\", \"wall_clock_seconds\": 8858.0, \"gpu_hours\": 2.46}, \"hypothesis\": \"Cross-model transfer: DeBERTa trained on LLaMA-8B wiki depth data can discriminate Qwen-7B wiki depth boundaries (K* transfer). Rerun of exp_cross_transfer_llama8b_to_qwen7b which crashed due to --gpu 1 device error.\", \"parent\": \"exp_cross_transfer_llama8b_to_qwen7b\", \"conclusion\": \"success\", \"metrics\": {\"K_star\": 3, \"2v3_auc_ci_lower\": 0.6124, \"theta\": 0.6, \"margin_pp\": 1.24}, \"completed_at\": \"2026-05-20T05:28:46.650Z\"}, \"exp_deberta_arxiv_qwen1b5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:12:10.106Z\", \"updated_at\": \"2026-05-20T03:50:38.093Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python scripts/run_deberta_arxiv.py\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"276481\", \"log_path\": \"~/runs/gen-depth-contamination/exp_deberta_arxiv_qwen1b5.log\", \"submitted_at\": \"2026-05-20T03:12:09.627Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/exp_024_arxiv/\", \"data_count\": 13200, \"model_name\": \"DeBERTa-v3-base\", \"seed\": \"5-fold GroupKFold\", \"hyperparams\": {\"epochs\": 3, \"batch_size\": 16, \"grad_accum\": 2, \"lr\": \"2e-5\", \"n_boot\": 10000, \"threshold\": 0.6}, \"checkpoint_path\": \"N/A (OOF predictions only)\", \"wall_clock_seconds\": 2247.8, \"gpu_hours\": 0.62}, \"hypothesis\": \"DeBERTa supervised classifier on arXiv domain yields K*=3 (matching OBD K*=3), confirming representation-independent domain ceiling holds across all 4 domains (C4 K*=2, wiki K*=3, code K*=2, arXiv K*=3).\", \"reproduce\": {\"finished_at\": \"2026-05-20T03:45:52.617Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T03:45:57.340301+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"K_star\": 4, \"0v1_auc\": 0.9997, \"1v2_auc\": 0.9214, \"2v3_auc\": 0.7446, \"3v4_auc\": 0.6238, \"4v5_auc\": 0.5771, \"3v4_ci_lower\": 0.6127, \"3v4_ci_upper\": 0.6349, \"theta\": 0.6}, \"completed_at\": \"2026-05-20T03:49:37.411Z\"}, \"exp_cross_transfer_llama8b_to_qwen7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:55:51.478Z\", \"updated_at\": \"2026-05-20T03:00:13.595Z\", \"spec\": {\"command\": \"python scripts/run_deberta_cross_transfer.py --train_model wiki_llama8b --test_model wiki_qwen7b --gpu 1\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"270133\", \"log_path\": \"~/runs/gen-depth-contamination/exp_cross_transfer_llama8b_to_qwen7b.log\", \"submitted_at\": \"2026-05-20T00:55:51.062Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/wiki_llama8b/ + wiki_qwen7b/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42, \"wall_clock_seconds\": 7462.5, \"gpu_hours\": 2.07}, \"hypothesis\": \"Cross-model transfer: DeBERTa trained on LLaMA-8B wiki depth data can discriminate Qwen-7B wiki depth boundaries (K* transfer), testing whether depth features are model-agnostic within wiki domain.\", \"conclusion\": \"failed\", \"failure_reason\": \"AssertionError: Invalid device id — --gpu 1 used but CUDA_VISIBLE_DEVICES only exposed 1 device. Need --gpu 0.\", \"checkpoint_path\": \"N/A - crashed before producing output\", \"log_path\": \"~/runs/gen-depth-contamination/exp_cross_transfer_llama8b_to_qwen7b.log\", \"completed_at\": \"2026-05-20T03:00:13.596Z\"}, \"exp_cross_transfer_qwen7b_to_llama8b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:55:49.779Z\", \"updated_at\": \"2026-05-20T02:59:59.419Z\", \"spec\": {\"command\": \"python scripts/run_deberta_cross_transfer.py --train_model wiki_qwen7b --test_model wiki_llama8b --gpu 0\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"270054\", \"log_path\": \"~/runs/gen-depth-contamination/exp_cross_transfer_qwen7b_to_llama8b.log\", \"submitted_at\": \"2026-05-20T00:55:49.362Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/wiki_qwen7b/ + wiki_llama8b/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42, \"wall_clock_seconds\": 7450.1, \"gpu_hours\": 2.07}, \"hypothesis\": \"Cross-model transfer: DeBERTa trained on Qwen-7B wiki depth data can discriminate LLaMA-8B wiki depth boundaries (K* transfer), testing whether depth features are model-agnostic within wiki domain.\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/wiki_qwen7b__to__wiki_llama8b.json\", \"log_path\": \"~/runs/gen-depth-contamination/exp_cross_transfer_qwen7b_to_llama8b.log\", \"metrics\": {\"kstar\": 3, \"kstar_indexing\": \"1-indexed\", \"pairwise_auc\": {\"0v1\": 0.9998, \"1v2\": 0.7384, \"2v3\": 0.6278, \"3v4\": 0.587, \"4v5\": 0.5519}, \"elapsed_s\": 3621}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T02:59:59.419Z\"}, \"exp_deberta_cross_transfer_gpu3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:45:58.698Z\", \"updated_at\": \"2026-05-20T00:52:16.950Z\", \"hypothesis\": \"Sub-experiment of exp_deberta_cross_transfer_wiki: GPU3 ran olmo↔llama8b, pythia↔mistral7b pairs (mistral7b pairs were bonus, qwen7b↔llama8b missing).\", \"conclusion\": \"success\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"command\": \"python scripts/run_deberta_cross_transfer.py\", \"pid\": \"208308\", \"data_path\": \"/root/gen-depth-contamination/data/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/gpu3.log\", \"reproduce\": {\"finished_at\": \"2026-05-20T00:50:30.198Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-20T00:50:32.377Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:50:36.649085+00:00\"}]}}, \"exp_deberta_cross_transfer_gpu2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:45:57.106Z\", \"updated_at\": \"2026-05-20T00:52:16.211Z\", \"hypothesis\": \"Sub-experiment of exp_deberta_cross_transfer_wiki: GPU2 ran olmo↔qwen7b, pythia→llama8b, llama8b→pythia pairs.\", \"conclusion\": \"success\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"command\": \"python scripts/run_deberta_cross_transfer.py\", \"pid\": \"208307\", \"data_path\": \"/root/gen-depth-contamination/data/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/gpu2.log\", \"reproduce\": {\"finished_at\": \"2026-05-20T00:50:20.459Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-20T00:50:22.410Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:50:27.489708+00:00\"}]}}, \"exp_deberta_cross_transfer_gpu1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:45:55.753Z\", \"updated_at\": \"2026-05-20T00:52:15.283Z\", \"hypothesis\": \"Sub-experiment of exp_deberta_cross_transfer_wiki: GPU1 ran pythia↔olmo and pythia↔qwen7b pairs.\", \"conclusion\": \"success\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"command\": \"python scripts/run_deberta_cross_transfer.py\", \"pid\": \"208306\", \"data_path\": \"/root/gen-depth-contamination/data/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/gpu1.log\", \"reproduce\": {\"finished_at\": \"2026-05-20T00:50:07.180Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-20T00:50:09.496Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:50:17.409046+00:00\"}]}}, \"exp_deberta_cross_transfer_wiki\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T22:23:41.514Z\", \"updated_at\": \"2026-05-20T00:45:03.982Z\", \"hypothesis\": \"DeBERTa cross-model transfer on wiki domain: if off-diagonal retention is high (>90%), depth signals are model-family invariant even with neural features; if wiki retention exceeds C4 retention, domain complexity affects transfer more than feature representation.\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\", \"cuda:2\", \"cuda:3\"], \"command\": \"python scripts/run_deberta_cross_transfer.py --all_pairs\", \"pid\": \"208306,208307,208308\", \"data_path\": \"/root/gen-depth-contamination/data/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"total_pairs_expected\": 12, \"completed_pairs\": 10, \"missing_pairs\": [\"qwen7b→llama8b\", \"llama8b→qwen7b\"], \"bonus_pairs\": [\"pythia→mistral7b (K*=2)\", \"mistral7b→pythia (K*=2)\"], \"kstar_distribution\": {\"K*=1\": 3, \"K*=2\": 5, \"K*=3\": 1}, \"kstar_1_pairs\": [\"pythia→olmo\", \"qwen7b→olmo\", \"llama8b→olmo\"], \"kstar_3_pair\": \"pythia→qwen7b\", \"kstar_2_pairs\": [\"olmo→qwen7b\", \"olmo→llama8b\", \"qwen7b→pythia\", \"llama8b→pythia\", \"pythia→llama8b\"], \"pattern\": \"All X→OLMo = K*=1. pythia→qwen7b highest at K*=3. GPU3 ran mistral7b pairs instead of expected qwen7b↔llama8b, causing 2 missing pairs.\", \"json_kstar_fix\": \"3 JSONs fixed +1 (pythia→olmo 0→1, olmo→qwen7b 1→2, olmo→llama8b 1→2)\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/deberta_cross_transfer/\", \"completed_at\": \"2026-05-20T00:44:09.679Z\"}, \"exp_deberta_c4_1b5_qwen_cont\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:14:07.803Z\", \"updated_at\": \"2026-05-20T00:43:44.526Z\", \"hypothesis\": \"C4 1.5B DeBERTa qwen_cont256 config (length-256 continuation): if K*=2, confirms boundary holds across generation strategies (base vs continuation) at 1.5B scale.\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"command\": \"python scripts/run_deberta_c4_1b5.py --config qwen_cont256 --gpu 0\", \"pid\": \"TBD\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_021_length_256/\", \"data_count\": 30000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_c4_1b5/qwen_cont256_oof.npz\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/deberta_c4_1b5_qwen_cont.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T00:41:45.752Z\", \"metrics\": {\"config\": \"qwen_cont256\", \"kstar\": 2, \"kstar_theta\": 0.6, \"pairwise_auc\": {\"0v1\": 0.9955, \"1v2\": 0.7194, \"2v3\": 0.5954, \"3v4\": 0.5689, \"4v5\": 0.5502}, \"ci_95\": {\"0v1\": [0.9944, 0.9965], \"1v2\": [0.712, 0.7273], \"2v3\": [0.587, 0.6028], \"3v4\": [0.5613, 0.5766], \"4v5\": [0.5431, 0.5577]}, \"obd_baseline\": {\"0v1\": 0.9914, \"1v2\": 0.6282, \"2v3\": 0.5556, \"3v4\": 0.5298, \"4v5\": 0.5137}, \"delta_vs_obd\": {\"1v2\": 0.0912}, \"key_finding\": \"C4 1.5B qwen_cont256 K*=2, boundary holds across continuation generation strategy.\"}}, \"exp_deberta_c4_1b5_pythia\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:14:05.964Z\", \"updated_at\": \"2026-05-20T00:19:10.196Z\", \"hypothesis\": \"C4 1.5B DeBERTa pythia_greedy config: apple-to-apple comparison with OBD Table 2. If K*=2 consistent with qwen_rw, confirms boundary is generator-invariant at 1.5B scale on C4.\", \"spec\": {\"server\": \"westd-42896\", \"gpu\": [\"cuda:1\"], \"command\": \"python scripts/run_deberta_c4_1b5.py --config pythia_greedy --gpu 1\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp020_pythia_greedy/\", \"data_count\": 30000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42, \"checkpoint_path\": \"n/a\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_c4_1b5/pythia_greedy.json\"}, \"metrics\": {\"config\": \"pythia_greedy\", \"kstar\": 2, \"kstar_theta\": 0.6, \"pairwise_auc\": {\"0v1\": 0.9998, \"1v2\": 0.9284, \"2v3\": 0.5419, \"3v4\": 0.5163, \"4v5\": 0.5098}, \"ci_95\": {\"0v1\": [0.9996, 0.9999], \"1v2\": [0.923, 0.9331], \"2v3\": [0.5354, 0.5486], \"3v4\": [0.509, 0.5237], \"4v5\": [0.5037, 0.516]}, \"obd_baseline\": {\"0v1\": 0.9992, \"1v2\": 0.8838, \"2v3\": 0.5342, \"3v4\": 0.5228, \"4v5\": 0.5162}, \"delta_vs_obd_1v2\": 0.0446, \"training_time_min\": 37.3}, \"conclusion\": \"success\", \"notes\": \"C4 1.5B DeBERTa pythia_greedy K*=2, consistent with qwen_rw K*=2. 1v2 AUC=0.9284 far exceeds OBD 0.8838 (+4.5pp), but 2v3=0.5419 still below θ=0.60, boundary unchanged. Notably pythia_greedy 1v2 much higher than qwen_rw (0.9284 vs 0.7052), likely due to greedy decoding being more distinguishable. OBD baseline also higher for pythia_greedy (0.8838 vs 0.6262). Results on westd-42896.\", \"completed_at\": \"2026-05-20T00:19:10.196Z\"}, \"exp_32b_c4_6class\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T22:31:06.464Z\", \"updated_at\": \"2026-05-20T00:15:44.463Z\", \"hypothesis\": \"32B DeBERTa 6-class rerun (depth 0-5) to fill 4v5 pair in paper table. If K* remains 2, confirms boundary even with full depth range; 4v5 AUC provides additional evidence of signal decay pattern.\", \"spec\": {\"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"command\": \"python run_deberta_6class.py --config exp_32b_c4\", \"pid\": \"139848\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/c4_32b\", \"data_count\": 30000, \"model_name\": \"microsoft/deberta-v3-base\", \"seed\": 42, \"note\": \"6-class rerun replacing 5-class exp_32b_c4, adds depth_5 for complete 4v5 pair\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_c4/exp_32b_c4_oof.npz\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/deberta_32b_6class.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T23:34:30.974Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T23:34:32.906Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T23:34:36.421721+00:00\"}]}, \"metrics\": {\"config\": \"exp_32b_c4\", \"kstar\": 2, \"kstar_indexing\": \"1-indexed\", \"num_classes\": 6, \"pairwise_auc\": {\"0v1\": 0.9923, \"1v2\": 0.6945, \"2v3\": 0.5978, \"3v4\": 0.5669, \"4v5\": 0.5426}, \"ci_95\": {\"0v1\": [0.991, 0.9936], \"1v2\": [0.6864, 0.7026], \"2v3\": [0.5898, 0.6058], \"3v4\": [0.559, 0.5746], \"4v5\": [0.5351, 0.5501]}, \"training_time_min\": 48.2}, \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/deberta_32b_6class.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_c4/exp_32b_c4_results.json\", \"notes\": \"Cron 误判为 failed（脚本不用 W&B），实际 5-fold 训练全部完成。K*=2 confirmed with 6 classes (depth 0-5)。2v3 AUC=0.5978 刚好低于 θ=0.60。4v5 AUC=0.5426 提供 signal decay 额外证据。\"}, \"exp_deberta_c4_1b5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T22:23:40.169Z\", \"updated_at\": \"2026-05-19T23:42:16.799Z\", \"hypothesis\": \"C4 1.5B DeBERTa apple-to-apple comparison with Table 2 OBD results: if DeBERTa K*=2 on same 1.5B C4 data as OBD, confirms boundary is intrinsic; if K*>2, quantifies neural vs handcrafted gap at 1.5B scale.\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/gen-depth-contamination && python scripts/run_deberta_c4_1b5.py --config qwen_rw --gpu 0\", \"pid\": \"255066\", \"data_path\": \"/root/gen-depth-contamination/data/exp016_qwen_base/\", \"data_count\": \"TBD\", \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42}, \"metrics\": {\"config\": \"qwen_rw\", \"kstar\": 2, \"kstar_theta\": 0.6, \"pairwise_auc\": {\"0v1\": 0.9923, \"1v2\": 0.7052, \"2v3\": 0.5988, \"3v4\": 0.5698, \"4v5\": 0.5475}, \"ci_95\": {\"0v1\": [0.9907, 0.9937], \"1v2\": [0.6977, 0.7129], \"2v3\": [0.5905, 0.6063], \"3v4\": [0.5626, 0.5774], \"4v5\": [0.5404, 0.5542]}, \"obd_baseline\": {\"0v1\": 0.987, \"1v2\": 0.6262, \"2v3\": 0.5496, \"3v4\": 0.5294, \"4v5\": 0.5182}, \"delta_vs_obd\": {\"1v2\": 0.079}, \"key_finding\": \"C4 1.5B DeBERTa qwen_rw K*=2, matching OBD K*=2. DeBERTa 1v2 +7.9pp vs OBD but does not extend K*. Note: only qwen_rw config done; pythia_greedy running on westd, qwen_cont256 starting on cqa1.\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T23:12:26.218Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T23:12:26.966Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T23:12:34.928421+00:00\"}]}, \"notes\": \"Cron 误判为 failed（脚本不用 W&B），实际完成。K*=2 confirmed on C4 1.5B data = OBD K*=2。DeBERTa 1v2 AUC=0.7052 vs OBD 0.6262 (+7.9pp)，但 2v3 仍低于 θ=0.60，无法突破 K* boundary。confirms intrinsic boundary on C4.\"}, \"exp_deberta_upperbound\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:29:11.448Z\", \"updated_at\": \"2026-05-19T22:05:28.928Z\", \"hypothesis\": \"DeBERTa-v3-base fine-tuned ordinal classifier as upper-bound baseline for 15D handcrafted features: if DeBERTa also yields K*=2 on C4 depth chains, the saturation boundary is near-intrinsic to generation process rather than a feature ceiling; if K*=3+, quantifies the gap between handcrafted and neural representations. Uses same 5-fold GroupKFold, pairwise AUC evaluation, θ=0.60 K* criterion.\", \"spec\": {\"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && python scripts/run_deberta_upperbound.py\", \"pid\": \"167144\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_upperbound.log\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/\", \"data_count\": 20000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_upperbound/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_upperbound.log\", \"metrics\": {\"wiki_pythia\": {\"kstar\": 3, \"0v1_auc\": 0.9993, \"1v2_auc\": 0.725, \"2v3_auc\": 0.6137, \"3v4_auc\": 0.5733, \"4v5_auc\": 0.5527}, \"wiki_olmo\": {\"kstar\": 1, \"0v1_auc\": 0.9999, \"1v2_auc\": 0.5183, \"2v3_auc\": 0.5048, \"3v4_auc\": 0.5021, \"4v5_auc\": 0.4989}, \"wiki_qwen7b\": {\"kstar\": 3, \"0v1_auc\": 0.9998, \"1v2_auc\": 0.7619, \"2v3_auc\": 0.6108, \"3v4_auc\": 0.5587, \"4v5_auc\": 0.5412}, \"wiki_llama8b\": {\"kstar\": 3, \"0v1_auc\": 0.9997, \"1v2_auc\": 0.7452, \"2v3_auc\": 0.5954, \"3v4_auc\": 0.5601, \"4v5_auc\": 0.5389}, \"wiki_mistral7b\": {\"kstar\": 3, \"0v1_auc\": 0.9998, \"1v2_auc\": 0.7483, \"2v3_auc\": 0.5552, \"3v4_auc\": 0.5434, \"4v5_auc\": 0.5298}, \"obd_baseline_bug_fixed\": true, \"wiki_olmo_obd_rerun\": {\"0v1\": 0.9933, \"1v2\": 0.4983, \"2v3\": 0.5041, \"3v4\": 0.4986, \"4v5\": 0.5089}, \"key_finding\": \"Wiki DeBERTa K*=3 for 4/5 configs (pythia/qwen7b/llama8b/mistral7b), exceeding OBD K*=2. DeBERTa breaks OBD boundary on wiki domain. OLMo K*=1 anomalous (near-random 1v2). OBD baseline bug for olmo fixed (was copy of pythia).\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:58:49.707Z\"}, \"exp_32b_c4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:56:48.122Z\", \"updated_at\": \"2026-05-19T21:55:27.105Z\", \"hypothesis\": \"Scale-dependent K* on C4: Qwen2.5-32B fp16 continuation on C4 web text 的 K* 是否仍 = 2？验证 K*=2 dominant mode 在 32B scale 是否稳定（已确认 1.5B/7B/8B/14B 均 K*=2），排除 scale ceiling effect。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_arXiv_llama8b\", \"server\": \"westd-42896\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-42896\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T19:37:31.096Z\", \"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-32B --data_dir data/exp_32b_c4 --results_dir results/exp_32b_c4 --num_samples 5000 --max_depth 5 --batch_size 2 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"finished_at\": \"2026-05-19T21:33:12.076Z\", \"training_hours\": 49.93}, \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-32B --data_dir data/exp_32b_c4 --results_dir results/exp_32b_c4 --num_samples 5000 --max_depth 5 --batch_size 2 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:1\"], \"pid\": \"44715\", \"log_path\": \"~/runs/gen-depth-contamination/exp_32b_c4.log\", \"submitted_at\": \"2026-05-18T07:04:19.556Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_32b_c4\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-32B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_32b_c4/\", \"wall_clock_seconds\": 139867.5, \"gpu_hours\": 38.85}, \"pid\": \"14637\", \"log_path\": \"~/runs/gen-depth-contamination/exp_32b_c4.log\", \"notes\": \"Resubmit #2 (2026-05-18T07:05): killed at depth 2 18% per Director, 72h timeout. depth 0-1 complete (5000 lines each), pipeline auto-skips. PID 44715 cuda:1.\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T21:33:15.741057+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"lgbm_kstar\": 2, \"deberta_kstar\": 2, \"kstar_theta\": 0.6, \"scale\": \"32B\", \"domain\": \"C4\", \"n_docs\": 5000, \"max_depth\": 5, \"key_finding\": \"Qwen2.5-32B C4 K*=2, confirming scale-invariance of K*=2 dominant mode from 1.5B to 32B. Both LightGBM and DeBERTa classifiers agree on K*=2.\"}, \"completed_at\": \"2026-05-19T21:55:27.105Z\"}, \"exp_deberta_c4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T19:27:44.088Z\", \"updated_at\": \"2026-05-19T20:30:48.238Z\", \"hypothesis\": \"DeBERTa-v3-base fine-tuned on raw text provides an upper-bound for C4 depth distinguishability compared to 15D LightGBM on handcrafted features. Pairwise AUC should exceed LightGBM at all depth pairs since the model has access to full lexical/semantic signal.\", \"parent\": \"exp_deberta_upperbound\", \"spec\": {\"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && HF_HOME=/root/autodl-tmp/.hf_cache python scripts/run_deberta_c4.py\", \"pid\": \"130789\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/\", \"data_count\": 55000, \"model_name\": \"DeBERTa-v3-base\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_deberta_c4/train.log\", \"checkpoint_path\": \"results/exp_deberta_c4/\", \"checkpoint_source\": \"microsoft/deberta-v3-base (pretrained)\", \"eval_data\": \"C4 depth chains (exp_14b_c4: 30k, exp_32b_c4: 25k)\"}, \"conclusion\": \"success\", \"metrics\": {\"pairwise_auc\": {\"0v1\": 0.9941, \"1v2\": 0.6781, \"2v3\": 0.5895, \"3v4\": 0.5651, \"4v5\": 0.5485}, \"ci_95\": {\"0v1\": [0.993, 0.9951], \"1v2\": [0.6696, 0.6866], \"2v3\": [0.5814, 0.5979], \"3v4\": [0.5573, 0.5732], \"4v5\": [0.5411, 0.5562]}, \"f1_at_050\": {\"0v1\": 0.9352, \"1v2\": 0.6751, \"2v3\": 0.6607, \"3v4\": 0.6204, \"4v5\": 0.2869}, \"kstar\": 2, \"kstar_theta\": 0.6, \"config\": \"exp_14b_c4\", \"n_samples\": 30000, \"n_docs\": 5000, \"bootstrap_resamples\": 10000, \"training_time_min\": 48.3}, \"notes\": \"DeBERTa K*=2 = LightGBM K*=2 on C4 14B, confirming representation-independent boundary. 86M-param fine-tuned neural classifier cannot extend K* beyond 2. Worker script reported K*=1 (off-by-one bug in K* calculation logic), corrected to K*=2 based on raw CI data: 1v2 CI lower=0.6696 > θ=0.60.\", \"completed_at\": \"2026-05-19T20:30:48.238Z\"}, \"exp_code_qwen7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T00:30:13.401Z\", \"updated_at\": \"2026-05-19T12:15:37.664Z\", \"hypothesis\": \"Qwen2.5-7B code domain K* measurement: Qwen family scale invariance test on CodeSearchNet Python. Pythia Code K*=1 弱化了跨模型一致性。Qwen-7B 测试两个方向：(1) Qwen 家族内 Code 的 scale invariance（1.5B K*=2, 7B K*=?），(2) 若 LLaMA/Mistral 也 K*=1，Qwen-7B K*=2 能维持 \\\"code-competent models reach K*=2\\\" 叙事。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_code_pythia1b4\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && source /root/miniconda3/bin/activate && HF_ENDPOINT=https://hf-mirror.com python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --data_dir data/exp_code_qwen7b --results_dir results/exp_code_qwen7b --num_samples 5000 --max_depth 5 --batch_size 4 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"114228\", \"log_path\": \"~/runs/gen-depth-contamination/exp_code_qwen7b.log\", \"submitted_at\": \"2026-05-19T01:29:00Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_code_qwen7b\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-7B\", \"seed\": 42, \"checkpoint_source\": \"exp_code_qwen1b5\", \"eval_data\": \"CodeSearchNet Python 5000 docs\", \"wall_clock_seconds\": 38608.5, \"gpu_hours\": 10.72}, \"notes\": \"Attempts 1-3 failed: huggingface.co unreachable (000), httpx client closed during datasets.load_dataset. Attempt 4 success: copied depth_0.jsonl from exp_code_qwen1b5 (MD5 match), set HF_ENDPOINT=https://hf-mirror.com. PID 114228, GPU util 96%, 15211/24564 MiB. nvidia-smi verified.\", \"reproduce\": {\"finished_at\": \"2026-05-19T12:12:26.097Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T12:12:28.503Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T12:12:31.991515+00:00\"}]}, \"metrics\": {\"pairwise_auc\": {\"0v1\": {\"mean\": 0.9051, \"ci95_half\": 0.0043, \"folds\": [0.9073, 0.9012, 0.912, 0.9049, 0.9003]}, \"1v2\": {\"mean\": 0.7276, \"ci95_half\": 0.0055, \"folds\": [0.7377, 0.7254, 0.724, 0.722, 0.7289]}, \"2v3\": {\"mean\": 0.5368, \"ci95_half\": 0.0145, \"folds\": [0.5179, 0.5332, 0.5275, 0.5462, 0.5593]}, \"3v4\": {\"mean\": 0.509, \"ci95_half\": 0.0055, \"folds\": [0.5029, 0.5054, 0.5085, 0.5092, 0.5191]}, \"4v5\": {\"mean\": 0.5139, \"ci95_half\": 0.0128, \"folds\": [0.5016, 0.5317, 0.5264, 0.509, 0.5007]}}, \"pairwise_jsd\": {\"0v1\": 0.061265, \"1v2\": 0.042256, \"2v3\": 0.00413, \"3v4\": 0.003198, \"4v5\": 0.003393}, \"k_star\": 2, \"ordinal\": {\"mae\": 1.2651, \"accuracy\": 0.3423}, \"top_features\": [{\"name\": \"freq_entropy\", \"importance\": 9730}, {\"name\": \"surp_d2_mean\", \"importance\": 9236.2}, {\"name\": \"surp_d1_mean\", \"importance\": 9126.2}, {\"name\": \"surp_d1_skew\", \"importance\": 8833.4}, {\"name\": \"surp_std\", \"importance\": 8110.2}, {\"name\": \"freq_kurtosis\", \"importance\": 7838.6}, {\"name\": \"surp_mean\", \"importance\": 7586}, {\"name\": \"surp_kurt\", \"importance\": 6769.2}, {\"name\": \"hapax_ratio\", \"importance\": 6636.4}, {\"name\": \"ttr\", \"importance\": 6332.6}]}}, \"exp_code_mistral7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:03:15.326Z\", \"updated_at\": \"2026-05-19T11:18:09.305Z\", \"hypothesis\": \"Mistral-7B code domain K* measurement: Mistral-7B-v0.3 continuation on CodeSearchNet Python subset. Mistral 是唯一展现极端 domain dependence 的模型（C4 K*=1, arXiv K*=3）。若 code K*=2（与 Qwen/LLaMA 一致）→ code K* domain-governed, Mistral one-wash 仅限 C4。若 code K*=1 → one-wash 是 model-intrinsic property for non-academic text。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_code_qwen1b5\", \"spec\": {\"command\": \"cd /root/autodl-tmp/gen-depth-contamination && source /root/miniconda3/bin/activate && python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/mistralai/Mistral-7B-v0___3 --data_dir data/exp_code_mistral7b --results_dir results/exp_code_mistral7b --num_samples 5000 --max_depth 5 --batch_size 4 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"107037\", \"log_path\": \"~/runs/gen-depth-contamination/exp_code_mistral7b.log\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_code_mistral7b\", \"data_count\": 5000, \"model_name\": \"Mistral-7B-v0.3\", \"seed\": 42, \"checkpoint_source\": \"exp_code_qwen1b5\", \"eval_data\": \"CodeSearchNet Python 5000 docs\"}, \"notes\": \"Log writes to /dev/pts/3 (terminal session), not a file. Progress inferred from data dir: depth_1.jsonl done (5500 lines), depth_2 in progress. No persistent log file for post-mortem analysis.\", \"reproduce\": {\"finished_at\": \"2026-05-19T11:05:15.743Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed. Diagnostic worker dispatched to check logs, partial output, OOM/disk issues.\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:05:15.059Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T11:05:21.025715+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_code_mistral7b/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_code_mistral7b/summary.txt\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9191, \"1v2\": 0.6152, \"2v3\": 0.5293, \"3v4\": 0.5286, \"4v5\": 0.5099}, \"pairwise_auc_ci\": {\"0v1\": 0.0017, \"1v2\": 0.012, \"2v3\": 0.0091, \"3v4\": 0.0104, \"4v5\": 0.006}, \"pairwise_jsd\": {\"0v1\": 0.046984, \"1v2\": 0.011845, \"2v3\": 0.003717, \"3v4\": 0.003206, \"4v5\": 0.003083}, \"ordinal_mae\": 1.3191, \"ordinal_accuracy\": 0.3243, \"top3_features\": [\"freq_entropy\", \"surp_d2_mean\", \"surp_d1_mean\"]}}, \"exp_code_llama8b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:36:19.645Z\", \"updated_at\": \"2026-05-19T08:15:39.198Z\", \"hypothesis\": \"Code domain (Python) cross-model K* validation: LLaMA-3.1-8B continuation on CodeSearchNet Python subset (Husain et al. 2019). 验证 code domain K* 跨模型一致性（与 exp_code_qwen1b5 对比）。如果 K* 一致，确认 code domain K* 是 domain-governed 而非 model-specific。5500 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_code_qwen1b5\", \"notes\": \"Generation completed normally (11.37 GPU-hours). Analysis step crashed on M010 bug (int(doc_id) on string 'code_py_0'). Bug was already patched in code (try/except at line 462-466). Worker re-ran analysis only → K*=2 confirmed. Results in results/exp_code_llama8b/.\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && source /root/miniconda3/bin/activate && python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/LLM-Research/Meta-Llama-3___1-8B --data_dir data/exp_code_llama8b --results_dir results/exp_code_llama8b --num_samples 5000 --max_depth 5 --batch_size 4 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"96335\", \"log_path\": \"~/runs/gen-depth-contamination/exp_code_llama8b.log\", \"submitted_at\": \"2026-05-18T20:43:36.548Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/code_python_seed\", \"data_count\": 5000, \"model_name\": \"LLaMA-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"exp_code_qwen1b5\", \"eval_data\": \"CodeSearchNet Python 5500 docs\", \"wall_clock_seconds\": 40928.2, \"gpu_hours\": 11.37}, \"reproduce\": {\"finished_at\": \"2026-05-19T08:05:42.229Z\"}, \"failure_reason\": \"Traceback → ^^^^^^^^^^^^^^^^^^^^^^^^^^^^ File \\\"/root/autodl-tmp/gen-depth-contamination/scripts/run_pipeline.py\\\", line 462, in run_analysis # Support both integer and string doc_ids ^^^^^^^^^^^^^^^^ ValueError: invalid literal for int() with base 10: 'code_py_0'\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T08:05:44.712Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T08:05:48.414385+00:00\"}]}, \"metrics\": {\"K_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9161, \"1v2\": 0.7394, \"2v3\": 0.5112, \"3v4\": 0.52, \"4v5\": 0.4996}, \"pairwise_auc_std\": {\"0v1\": 0.004, \"1v2\": 0.0101, \"2v3\": 0.0095, \"3v4\": 0.0137, \"4v5\": 0.0069}, \"pairwise_jsd\": {\"0v1\": 0.060406, \"1v2\": 0.047034, \"2v3\": 0.003473, \"3v4\": 0.003026, \"4v5\": 0.002892}, \"ordinal_mae\": 1.2542, \"ordinal_accuracy\": 0.3485, \"top_features\": [\"freq_entropy\", \"surp_d1_mean\", \"surp_d2_mean\"]}}, \"exp_code_qwen1b5_pythia_scorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:30:03.239Z\", \"updated_at\": \"2026-05-19T06:55:26.175Z\", \"hypothesis\": \"Code domain scorer confound control: Qwen-1.5B Code K*=2 uses same-family Qwen scorer. D060 Wikipedia showed Qwen scorer inflates AUC by +0.005~0.027. If Pythia-1.4B scorer yields K*=2 on same Qwen Code text, confirms K*=2 is text-intrinsic (not scorer artifact). If K*=1, Qwen Code K*=2 is partially scorer-driven, weakening domain ceiling claim. Cross-family scorer validation on existing exp_code_qwen1b5 depth 0-5 data.\", \"parent\": \"exp_code_qwen1b5\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"spec\": {\"checkpoint_path\": \"results/exp_code_qwen1b5_pythia_scorer/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_code_qwen1b5_pythia_scorer.log\"}, \"pid\": \"131475\", \"log_path\": \"~/runs/gen-depth-contamination/exp_code_qwen1b5_pythia_scorer.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/gen-depth-contamination && bash scripts/exp_code_qwen1b5_pythia_scorer.sh\\\"\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-19T06:51:51.622Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T06:51:55.524732+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 2, \"theta\": 0.6, \"auc_0v1\": 0.9076, \"auc_1v2\": 0.7197, \"auc_2v3\": 0.5308, \"auc_3v4\": 0.5236, \"auc_4v5\": 0.5084, \"jsd_0v1\": 0.065423, \"jsd_1v2\": 0.035809, \"jsd_2v3\": 0.004315, \"jsd_3v4\": 0.003182, \"jsd_4v5\": 0.003047, \"ordinal_mae\": 1.2578, \"ordinal_accuracy\": 0.3433, \"scorer\": \"pythia-1.4b\"}, \"notes\": \"Code domain K*=2 confirmed scorer-independent. Pythia-1.4B scorer reproduces K*=2 on Qwen-1.5B Code text (same as Qwen self-scorer). AUC deltas vs original: 0v1 Δ=-0.031, 1v2 Δ=-0.019 (minor drop, Pythia slightly weaker feature extractor), 2v3 Δ=+0.001 (identical). Boundary transition 1v2→2v3 robust: 0.7197→0.5308, clear drop below θ=0.6. JSD pattern consistent: sharp collapse at depth 2→3. Combined with arXiv cross-scorer results (LLaMA/Mistral K*=3 preserved), confirms generational depth K* is a text-intrinsic property governed by domain complexity, not scorer choice.\", \"completed_at\": \"2026-05-19T06:55:26.175Z\"}, \"exp_pythia_retrain_depth7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:53:18.835Z\", \"updated_at\": \"2026-05-19T03:46:00.139Z\", \"hypothesis\": \"Pythia-1.4B retrain-chain depth extension to 7: 验证 retrain-chain K* >> prompt-chain K* 是否跨模型家族一致（Qwen retrain K*≥7）。如果 Pythia 也 K*≥5-7，confirms retrain artifacts are model-independent。C4 5K docs, LoRA rank=16 alpha=32, depth 0-7。\", \"parent\": \"exp_qwen_retrain_depth7\", \"spec\": {\"command\": \"HF_ENDPOINT=https://hf-mirror.com CUDA_VISIBLE_DEVICES=0 python scripts/exp_pythia_retrain_depth7.py --device cuda:0\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_008_retrain_chain\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b\", \"seed\": 42, \"checkpoint_source\": \"exp_008_retrain_chain depth 0-4 data (extending to depth 5-7)\", \"eval_data\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_008_retrain_chain/features.csv\", \"gpu\": [\"cuda:0\"], \"pid\": \"115855\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp_pythia_retrain_depth7_nohup.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_pythia_retrain_depth7\"}, \"notes\": \"Actual log path: /root/autodl-tmp/gen-depth-contamination/logs/exp_pythia_retrain_depth7_nohup.log (not ~/runs/). Fine-tuning 1250 steps completed, currently in generation phase. GPU util 53% normal for Pythia-1.4B small model.\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T03:45:55.351Z\", \"metrics\": {\"kstar\": 7, \"pairwise_auc\": {\"0v1\": 0.9844, \"1v2\": 0.947, \"2v3\": 0.8891, \"3v4\": 0.7999, \"4v5\": 0.6907, \"5v6\": 0.6497, \"6v7\": 0.634}, \"pairwise_auc_ci\": {\"0v1\": [0.9829, 0.9858], \"1v2\": [0.9418, 0.9522], \"2v3\": [0.8822, 0.896], \"3v4\": [0.7951, 0.8047], \"4v5\": [0.688, 0.6934], \"5v6\": [0.6429, 0.6565], \"6v7\": [0.6275, 0.6406]}, \"pairwise_jsd\": {\"0v1\": 0.1775, \"1v2\": 0.1286, \"2v3\": 0.1069, \"3v4\": 0.0643, \"4v5\": 0.0331, \"5v6\": 0.0271, \"6v7\": 0.0138}}}, \"exp_qwen_retrain_depth7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:08:52.105Z\", \"updated_at\": \"2026-05-19T01:10:25.114Z\", \"hypothesis\": \"Qwen2.5-1.5B retrain-chain extended to depth 7: K* measurement at higher depths. Retrain-chain with LoRA rank=16, alpha=32, 1 epoch per generation. Each depth uses independently trained LoRA merged before next generation. C4 5K docs, depth 0-7, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B (self-scoring). Extends exp_qwen_retrain_chain (depth 0-4).\", \"parent\": \"exp_qwen_retrain_chain\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path Qwen2.5-1.5B --max_depth 7 (retrain-chain extension)\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_qwen_retrain_chain_ext\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B\", \"seed\": 42, \"checkpoint_source\": \"exp_qwen_retrain_chain\", \"eval_data\": \"C4 5000 docs depth 0-7\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_qwen_retrain_chain_ext/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_qwen_retrain_chain_ext/summary.json\", \"metrics\": {\"k_star\": 7, \"theta\": 0.6, \"max_depth\": 7, \"analysis_method\": \"5-fold GroupKFold CV\", \"pairwise_auc\": {\"0v1\": {\"mean\": 0.9837, \"std\": 0.0019, \"ci_95\": [0.9821, 0.9854], \"folds\": [0.9832, 0.9821, 0.9837, 0.9823, 0.9873]}, \"1v2\": {\"mean\": 0.8971, \"std\": 0.0025, \"ci_95\": [0.8949, 0.8993], \"folds\": [0.8923, 0.8988, 0.8986, 0.8991, 0.8967]}, \"2v3\": {\"mean\": 0.8098, \"std\": 0.0052, \"ci_95\": [0.8052, 0.8144], \"folds\": [0.8086, 0.8074, 0.818, 0.8024, 0.8128]}, \"3v4\": {\"mean\": 0.76, \"std\": 0.0082, \"ci_95\": [0.7528, 0.7672], \"folds\": [0.7534, 0.7617, 0.7753, 0.7566, 0.7531]}, \"4v5\": {\"mean\": 0.7459, \"std\": 0.0091, \"ci_95\": [0.7379, 0.7538], \"folds\": [0.7429, 0.7562, 0.7521, 0.73, 0.7482]}, \"5v6\": {\"mean\": 0.7017, \"std\": 0.0068, \"ci_95\": [0.6958, 0.7076], \"folds\": [0.7006, 0.7077, 0.7104, 0.6915, 0.6984]}, \"6v7\": {\"mean\": 0.641, \"std\": 0.0039, \"ci_95\": [0.6376, 0.6445], \"folds\": [0.6419, 0.6349, 0.6464, 0.639, 0.643]}}, \"jsd\": {\"0v1\": 0.23005, \"1v2\": 0.103924, \"2v3\": 0.075049, \"3v4\": 0.065398, \"4v5\": 0.060509, \"5v6\": 0.034998, \"6v7\": 0.017652}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T01:10:20.209Z\", \"notes\": \"Qwen2.5-1.5B retrain-chain K*=7 (all 7 depth pairs AUC > θ=0.60). 6v7 AUC=0.641 (CI [0.638, 0.645]) is the tightest pair but still clears threshold. Depth 0-4 results consistent with exp_qwen_retrain_chain (AUC diff < 0.003). JSD decays from 0.230 (0v1) to 0.018 (6v7), suggesting convergence. AUC decay is sublinear: rapid initial drop (0v1→2v3: ~0.087/step), then deceleration (2v3→4v5: ~0.032/step), with continued decline (4v5→6v7: ~0.052/step). K* ceiling estimated at 7-8 based on extrapolation.\"}, \"exp_code_pythia1b4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:49:01.762Z\", \"updated_at\": \"2026-05-19T00:27:22.456Z\", \"hypothesis\": \"Pythia-1.4B on Code domain (Python/CodeSearchNet) will show K*=2 consistent with Qwen code domain results, indicating generalization depth saturation is model-independent for code data.\", \"parent\": \"exp_code_qwen1b5\", \"spec\": {\"command\": \"cd /root/autodl-tmp/gen-depth-contamination && source /root/miniconda3/bin/activate && python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_code_pythia1b4 --results_dir results/exp_code_pythia1b4 --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_code_pythia1b4\", \"data_count\": 5000, \"model_name\": \"Pythia-1.4B\", \"seed\": 42, \"checkpoint_source\": \"exp_code_qwen1b5\", \"eval_data\": \"CodeSearchNet Python 5000 docs\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_code_pythia1b4/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_code_pythia1b4/train.log\", \"metrics\": {\"k_star\": 1, \"theta\": 0.6, \"pairwise_auc\": {\"0v1\": {\"mean\": 0.9592, \"std\": 0.0036, \"folds\": [0.9576, 0.9576, 0.9657, 0.96, 0.9552]}, \"1v2\": {\"mean\": 0.5983, \"std\": 0.005, \"folds\": [0.601, 0.5884, 0.6, 0.5997, 0.6024]}, \"2v3\": {\"mean\": 0.5215, \"std\": 0.0128, \"folds\": [0.5236, 0.5124, 0.5311, 0.5024, 0.5381]}, \"3v4\": {\"mean\": 0.5152, \"std\": 0.012, \"folds\": [0.4981, 0.5327, 0.5092, 0.5123, 0.5238]}, \"4v5\": {\"mean\": 0.5046, \"std\": 0.0137, \"folds\": [0.4983, 0.4822, 0.5074, 0.5224, 0.5128]}}, \"jsd\": {\"0v1\": 0.070173, \"1v2\": 0.008211, \"2v3\": 0.003674, \"3v4\": 0.002902, \"4v5\": 0.002685}, \"ordinal\": {\"mae\": 1.3268, \"accuracy\": 0.3357}, \"top_features\": [\"freq_entropy\", \"surp_d1_mean\", \"surp_d2_mean\", \"surp_mean\", \"surp_d1_skew\"], \"features_csv\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_code_pythia1b4/features.csv\"}, \"completed_at\": \"2026-05-19T00:25:32.688Z\", \"notes\": \"Pythia-1.4B code domain K*=1 (1v2 AUC=0.5983, 0.17pp below θ=0.60). Hypothesis falsified: expected K*=2 consistent with Qwen. 3/5 folds above θ (0.601, 0.600, 0.602), mean borderline. Parallels Mistral C4 one-wash pattern. Suggests model capability modulates domain ceiling.\"}, \"exp_028_power_curve\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:53:26.909Z\", \"updated_at\": \"2026-05-18T23:01:26.449Z\", \"hypothesis\": \"Subsampling power analysis: K*=2 判定在 C4 上所需的最低样本量。在 n={500,1000,2000,3000,4000,5000} 下 10 次 random resample，每次 5-fold CV 计算 1v2 AUC。输出 power curve（K*=2 判定成功率 vs n）。验证类实验，回应 Reviewer 对 statistical power / sample size adequacy 的质疑。\", \"metrics\": {\"min_n_100pct\": 2000, \"n500_auc\": 0.5808, \"n500_rate\": 0.2, \"n1000_auc\": 0.5911, \"n1000_rate\": 0.3, \"n2000_auc\": 0.6101, \"n2000_rate\": 1, \"n3000_auc\": 0.6166, \"n3000_rate\": 1, \"n4000_auc\": 0.622, \"n4000_rate\": 1, \"n5000_auc\": 0.6288, \"n5000_rate\": 1}, \"conclusion\": \"success\", \"notes\": \"K*=2 detection on C4 requires minimum n=2000 docs for 100% success rate (10/10 resamples). Below n=2000 power drops sharply: n=1000 → 30%, n=500 → 20%. AUC variance monotonically decreases with n (0.018 at n=500 → 0.004 at n=4000). Feature data from exp016_qwen_base (C4, 5000 docs × 6 depths × 15 features). CPU-only, 86s runtime.\", \"spec\": {\"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_028_power_curve/\", \"command\": \"python scripts/exp_028_power_curve.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp016_qwen_base/features.csv\", \"data_count\": 30000, \"model_name\": \"N/A\", \"seed\": 42}, \"completed_at\": \"2026-05-18T23:01:26.449Z\"}, \"exp_qwen_retrain_chain\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:57:56.785Z\", \"updated_at\": \"2026-05-18T22:30:28.719Z\", \"hypothesis\": \"Qwen2.5-1.5B retrain-chain ecological validity: LoRA rank=16, alpha=32, 1 epoch per generation. Retrain-chain K* ≤ prompt-chain K*=2, confirming prompt-chain as conservative upper bound across a second architecture family (Qwen vs Pythia). C4 5K docs, depth 0-4, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B (self-scoring).\", \"parent\": \"exp_008_retrain_chain_v2\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/qwen_retrain_chain/lora_adapters/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_qwen_retrain_chain.log\"}, \"metrics\": {\"K_star_lower_bound\": 4, \"theta\": 0.6, \"auc_0v1\": 0.9838, \"auc_1v2\": 0.8969, \"auc_2v3\": 0.81, \"auc_3v4\": 0.7624, \"ci_0v1\": [0.982, 0.9855], \"ci_1v2\": [0.8937, 0.9001], \"ci_2v3\": [0.8052, 0.8147], \"ci_3v4\": [0.7543, 0.7706], \"ci_method\": \"5-fold CV\", \"jsd_0v1\": 0.2263, \"jsd_1v2\": 0.1046, \"jsd_2v3\": 0.0752, \"jsd_3v4\": 0.0654}, \"notes\": \"Qwen2.5-1.5B retrain-chain K*≥4 (all 4 pairs AUC >> θ=0.60). Bootstrap CI discarded due to data leakage (resampling broke GroupKFold structure, inflated AUC by +6.4pp). Using fold-based CI instead. Retrain-chain K*≥4 >> prompt-chain K*=2, contradicts conservative-upper-bound hypothesis but confirms retrain produces qualitatively different degradation pattern.\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:30:28.719Z\"}, \"exp_code_qwen1b5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:36:16.788Z\", \"updated_at\": \"2026-05-18T21:45:24.101Z\", \"hypothesis\": \"Code domain (Python) K* measurement: Qwen2.5-1.5B continuation on CodeSearchNet Python subset (Husain et al. 2019). Code 的高度结构化特性（语法约束、缩进、函数签名）应使代际退化慢于 C4 (K*≥2)，可能接近 arXiv (K*=3)。5500 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"notes\": \"Code domain (Python/CodeSearchNet) K*=2, same as C4. 1v2 AUC=0.7382 well above θ, 2v3 drops to 0.5300. Bug fix: run_pipeline.py:462 int(doc_id) patched for string IDs. Top features: freq_entropy, surp_d2_mean, surp_d1_mean. Data source: CodeSearchNet Python subset (Husain et al. 2019).\", \"spec\": {\"checkpoint_path\": \"N/A (pipeline experiment, no model checkpoint)\", \"log_path\": \"~/runs/gen-depth-contamination/exp_code_qwen1b5.log\"}, \"conclusion\": \"success\", \"metrics\": {\"K_star\": 2, \"theta\": 0.6, \"auc_0v1\": 0.9388, \"auc_1v2\": 0.7382, \"auc_2v3\": 0.53, \"auc_3v4\": 0.5022, \"auc_4v5\": 0.5219, \"ci_0v1\": [0.929, 0.949], \"ci_1v2\": [0.709, 0.767], \"ci_2v3\": [0.514, 0.546], \"jsd_0v1\": 0.0814, \"jsd_1v2\": 0.0443, \"jsd_2v3\": 0.0038, \"ordinal_accuracy\": 0.359, \"ordinal_mae\": 1.204}, \"completed_at\": \"2026-05-18T21:45:24.101Z\"}, \"exp_olmo_retrain_chain\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:08:07.671Z\", \"updated_at\": \"2026-05-18T16:27:30.792Z\", \"hypothesis\": \"OLMo-1B retrain-chain (LoRA rank=16, 1 epoch per generation) on C4 produces K* ≤ 2, confirming prompt-chain as conservative upper bound for K*.\", \"parent\": \"exp_002\", \"spec\": {\"command\": \"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp_olmo_retrain_chain.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/olmo_retrain_chain\", \"data_count\": 5000, \"model_name\": \"allenai/OLMo-1B-hf\", \"seed\": 42, \"checkpoint_source\": \"allenai/OLMo-1B-hf\", \"eval_data\": \"C4 validation (5000 docs)\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T16:27:30.792Z\"}, \"exp_028_subsampling_power\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:30:47.472Z\", \"updated_at\": \"2026-05-18T13:31:41.053Z\", \"hypothesis\": \"C4 K*=2 信号的 minimum sample size: 在 n={1000..5000} 范围内，GroupKFold(5) 1v2 AUC 是否稳定超过 θ=0.60？确定可靠判定 K*=2 所需的最小样本量。\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/c4_power_curve/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/c4_power_curve/power_curve_results.json\", \"metrics\": {\"n_1000\": {\"mean_auc\": 0.608, \"std\": 0.012, \"detection_prob\": 0.9}, \"n_2500\": {\"mean_auc\": 0.618, \"std\": 0.006, \"detection_prob\": 1}, \"n_5000\": {\"mean_auc\": 0.629, \"std\": 0, \"detection_prob\": 1}, \"key_finding\": \"n>=2500 gives 100% reliable K*=2 detection. n=1000 already 90%. Signal is robust, not large-sample artifact.\"}, \"spec\": {\"command\": \"python scripts/c4_power_curve.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/results/ (exp-016 features)\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B (scorer)\", \"seed\": \"10 random trials per n\", \"checkpoint_source\": \"exp-016 feature vectors\", \"eval_data\": \"GroupKFold(5) pairwise classification, n={1000..5000}\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T13:31:41.053Z\"}, \"exp_026_arxiv_filtering\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T10:19:57.768Z\", \"updated_at\": \"2026-05-18T11:20:35.820Z\", \"hypothesis\": \"Graduated depth weighting (α=0.9^d) on arXiv depth chains will outperform both no-filter and binary-cut baselines on downstream benchmarks (MMLU, HellaSwag), because it preserves useful signal from deeper generations while down-weighting accumulated contamination, rather than discarding data entirely.\", \"parent\": \"exp_006_graduated_filtering\", \"spec\": {\"command\": \"bash scripts/run_exp026.sh\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_024_arxiv/\", \"data_count\": 13200, \"model_name\": \"Qwen2.5-1.5B\", \"seed\": \"42,123,456,789,1024\", \"gpu\": \"cuda:0,cuda:1,cuda:2\", \"strategies\": \"no_filter,binary,graduated_a09\", \"lora_rank\": 4, \"lora_alpha\": 8, \"pid\": 27516, \"checkpoint_source\": \"lora_merge_per_run\", \"eval_data\": \"mmlu,hellaswag (lm-eval-harness)\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_026_arxiv_filtering/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp_026_arxiv_filtering.log\", \"metrics\": {\"runs_completed\": \"15/15\", \"strategies\": [\"no_filter\", \"binary\", \"graduated_a09\"], \"seeds\": [42, 123, 456, 789, 1024], \"mmlu\": {\"no_filter\": \"0.5899±0.0008\", \"binary\": \"0.5876±0.0004\", \"graduated_a09\": \"0.5900±0.0011\"}, \"hellaswag\": {\"no_filter\": \"0.6600±0.0002\", \"binary\": \"0.6642±0.0004\", \"graduated_a09\": \"0.6599±0.0003\"}, \"delta_vs_no_filter\": {\"binary_mmlu\": \"-0.0023\", \"binary_hellaswag\": \"+0.0042\", \"graduated_mmlu\": \"+0.0001\", \"graduated_hellaswag\": \"-0.0001\"}, \"key_finding\": \"All three strategies produce nearly identical results. Graduated ≈ no_filter; binary slightly better on HellaSwag (+0.004) but worse on MMLU (-0.002). Hypothesized ordering graduated>binary>no_filter NOT confirmed.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T11:20:35.820Z\"}, \"exp_027_latex_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T10:19:59.624Z\", \"updated_at\": \"2026-05-18T10:41:35.226Z\", \"hypothesis\": \"arXiv K*=3 不依赖 LaTeX 格式特征。去除 LaTeX markup 后重新提取 15D features 并跑 pairwise classification，K* 应仍=3，排除 LaTeX 语法作为 confound。\", \"parent\": \"exp_024_arxiv_depth_chain\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_027_latex_ablation/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_027_latex_ablation/summary.txt\", \"metrics\": {\"k_star\": 3, \"k_star_preserved\": true, \"pairwise_auc_original\": {\"0v1\": 0.9948, \"1v2\": 0.8581, \"2v3\": 0.6436, \"3v4\": 0.544, \"4v5\": 0.5299}, \"pairwise_auc_stripped\": {\"0v1\": 0.9948, \"1v2\": 0.8297, \"2v3\": 0.6229, \"3v4\": 0.5468, \"4v5\": 0.5476}, \"auc_delta\": {\"0v1\": 0, \"1v2\": -0.028, \"2v3\": -0.021, \"3v4\": 0.003, \"4v5\": 0.018}, \"latex_reduction_by_depth\": {\"depth_0\": \"0.6%\", \"depth_5\": \"4.4%\"}, \"key_finding\": \"K*=3 preserved after LaTeX removal. 2v3 AUC 0.6436→0.6229 (still >θ=0.60). LaTeX format is NOT a confound.\"}, \"spec\": {\"command\": \"python scripts/exp027_latex_ablation.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_024_arxiv/\", \"data_count\": 13200, \"model_name\": \"Qwen2.5-1.5B (scorer)\", \"seed\": 42, \"checkpoint_source\": \"exp_024_arxiv_depth_chain\", \"eval_data\": \"GroupKFold(5) pairwise classification\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T10:41:35.226Z\"}, \"exp_025_pythia_filtering\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T08:04:54.965Z\", \"updated_at\": \"2026-05-18T09:51:02.931Z\", \"hypothesis\": \"Filtering strategy ordering (binary > graduated > no-filter) 在 Pythia-1.4B 上与 Qwen 一致，验证 K*=2 对 curation 策略选择的跨模型预测价值。Pythia-1.4B LoRA rank=8 continued pretraining on C4 depth chain, 3 strategies × 3 seeds, eval MMLU+HellaSwag.\", \"parent\": \"exp_006_graduated_filtering\", \"spec\": {\"command\": \"bash scripts/run_exp025.sh (3 strategies × 3 seeds, 9 runs in 3 batches, 4 GPUs parallel per batch)\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp020_pythia_nuc09/\", \"data_count\": 30000, \"model_name\": \"Pythia-1.4B\", \"seed\": \"42,123,456\", \"checkpoint_source\": \"EleutherAI/pythia-1.4b (HuggingFace, base model for LoRA)\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\"}, \"notes\": \"Data source fixed: greedy → nuc09. Old processes killed (6 procs). Resubmitted 2026-05-18T08:27 via nohup (not submit_training_job). PID 15687, cqa1 cuda:0-3, 9 runs in 3 batches (4 parallel per batch). Cron registered for monitoring.\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_025_pythia_filtering/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp025/\", \"metrics\": {\"runs_completed\": \"9/9\", \"strategies\": [\"no_filter\", \"binary_ours\", \"graduated_a09\"], \"seeds\": [42, 123, 456], \"mmlu\": {\"no_filter\": \"0.2568±0.0012\", \"binary_ours\": \"0.2585±0.0004\", \"graduated_a09\": \"0.2561±0.0009\"}, \"hellaswag\": {\"no_filter\": \"0.5250±0.0008\", \"binary_ours\": \"0.5251±0.0001\", \"graduated_a09\": \"0.5253±0.0007\"}, \"delta_vs_no_filter\": {\"binary_ours_mmlu\": \"+0.0017\", \"binary_ours_hellaswag\": \"+0.0000\", \"graduated_a09_mmlu\": \"-0.0007\", \"graduated_a09_hellaswag\": \"+0.0003\"}, \"key_finding\": \"All three filtering strategies produce nearly identical results on Pythia-1.4B. Deltas are within noise (max 0.0017 MMLU). Hypothesized ordering binary>graduated>no_filter NOT confirmed.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T09:51:02.931Z\"}, \"exp_14b_c4\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T14:56:44.366Z\", \"updated_at\": \"2026-05-18T08:37:25.809Z\", \"hypothesis\": \"Scale-dependent K* on C4: Qwen2.5-14B fp16 continuation on C4 web text 的 K* 是否仍 = 2？验证 K*=2 dominant mode 在 14B scale 是否稳定（已确认 1.5B/7B/8B 均 K*=2），排除 scale ceiling effect。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_arXiv_llama8b\", \"server\": \"westd-42896\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-42896\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T17:08:43.246Z\", \"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-14B --data_dir data/exp_14b_c4 --results_dir results/exp_14b_c4 --num_samples 5000 --max_depth 5 --batch_size 4 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"finished_at\": \"2026-05-18T08:21:21.247Z\", \"training_hours\": 15.21}, \"failure_reason\": \"EXIT_CODE=124 (timeout — exceeded timeout_hours)\", \"completed_at\": \"2026-05-18T05:09:04.625Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:09:08.254971+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T08:21:24.534646+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-14B --data_dir data/exp_14b_c4 --results_dir results/exp_14b_c4 --num_samples 5000 --max_depth 5 --batch_size 4 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"server\": \"westd-42896\", \"gpu\": [\"cuda:0\"], \"pid\": \"39497\", \"log_path\": \"~/runs/gen-depth-contamination/exp_14b_c4.log\", \"submitted_at\": \"2026-05-18T05:12:11.079Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11638.0, \"gpu_hours\": 3.23}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9598, \"1v2\": 0.621, \"2v3\": 0.5494, \"3v4\": 0.5243, \"4v5\": 0.5154}, \"pairwise_jsd\": {\"0v1\": 0.1097, \"1v2\": 0.0112, \"2v3\": 0.0062, \"3v4\": 0.0044, \"4v5\": 0.0036}, \"bootstrap_ci\": {\"0v1\": [0.9564, 0.963], \"1v2\": [0.6119, 0.6304], \"2v3\": [0.5392, 0.5594], \"3v4\": [0.514, 0.5346], \"4v5\": [0.5045, 0.5265]}, \"permutation_p\": {\"0v1\": \"<0.001\", \"1v2\": \"<0.001\", \"2v3\": \"<0.001\", \"3v4\": \"<0.001\", \"4v5\": \"<0.001\"}, \"k_star_statistically_confirmed\": true, \"ordinal_mae\": 1.2266, \"ordinal_accuracy\": 0.3497, \"top_features\": [\"freq_entropy\", \"surp_d1_skew\", \"surp_std\", \"surp_d1_mean\", \"surp_d2_mean\"], \"key_finding\": \"K*=2 confirmed at 14B scale with bootstrap CI. 1v2 CI lower (0.6119) > theta=0.60; 2v3 CI upper (0.5594) < theta=0.60. All permutation p<0.001.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_14b_c4/\"}, \"exp_arXiv_mistral7b_crossscorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T02:44:21.237Z\", \"updated_at\": \"2026-05-18T03:04:46.219Z\", \"hypothesis\": \"arXiv cross-scorer (Mistral-7B): Pythia scorer 验证 Mistral arXiv K*=3 是否 scorer-independent。\", \"parent\": \"exp_wiki_scorer_confound\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && mkdir -p data/exp_arXiv_mistral7b_crossscorer && for d in 0 1 2 3 4 5; do ln -sf /root/autodl-tmp/gen-depth-contamination/data/exp_arXiv_mistral7b/depth_\\\\${d}.jsonl data/exp_arXiv_mistral7b_crossscorer/depth_\\\\${d}.jsonl; done && mkdir -p results/exp_arXiv_mistral7b_crossscorer && HF_HOME=/root/autodl-tmp/.hf_cache TRANSFORMERS_CACHE=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --scorer_path /root/autodl-tmp/.hf_cache/hub/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_arXiv_mistral7b_crossscorer --results_dir results/exp_arXiv_mistral7b_crossscorer --num_samples 2200 --max_depth 5 --batch_size 16 --generation_mode continuation --skip_generation\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"196053\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_mistral7b_crossscorer.log\", \"submitted_at\": \"2026-05-18T02:44:57.643Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 2200, \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_arXiv_mistral7b\", \"model_name\": \"Mistral-7B (generator) + Pythia-1.4B (scorer)\", \"seed\": 42, \"checkpoint_source\": \"exp_arXiv_mistral7b\", \"eval_data\": \"arXiv depth 0-5 generated by Mistral-7B (from exp_arXiv_mistral7b)\", \"checkpoint_path\": \"results/exp_arXiv_mistral7b_crossscorer/\", \"wall_clock_seconds\": 1117.5, \"gpu_hours\": 0.31}, \"reproduce\": {\"finished_at\": \"2026-05-18T03:00:29.276Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T03:00:37.583555+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 3, \"scorer\": \"pythia-1.4b\", \"auc_0v1\": 0.9798, \"auc_1v2\": 0.8141, \"auc_2v3\": 0.6075, \"auc_3v4\": 0.5489, \"auc_4v5\": 0.5391, \"jsd_0v1\": 0.135575, \"jsd_1v2\": 0.078, \"jsd_2v3\": 0.020452, \"jsd_3v4\": 0.010992, \"jsd_4v5\": 0.008831, \"ordinal_mae\": 0.9061, \"ordinal_accuracy\": 0.4412}, \"completed_at\": \"2026-05-18T03:03:35.138Z\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_mistral7b_crossscorer.log\", \"notes\": \"Pythia-1.4B cross-scorer confirms K*=3 for Mistral-7B arXiv, matching Qwen-1.5B original. Max AUC delta = 0.02 (at 2v3). arXiv Mistral K*=3 is scorer-independent. Contrasts with Wikipedia where scorer choice affected K*.\"}, \"exp_arXiv_llama8b_crossscorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T02:44:19.881Z\", \"updated_at\": \"2026-05-18T03:04:36.609Z\", \"hypothesis\": \"Replacing Qwen-1.5B scorer with Pythia-1.4B on arXiv LLaMA-8B depth 0-5 texts should yield the same K*=3 boundary, because the saturation signal is a genuine property of LLaMA-8B generated text rather than a scorer family artifact\", \"parent\": \"exp_wiki_scorer_confound\", \"spec\": {\"command\": \"skip_generation scoring with Pythia-1.4B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"195907\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_llama8b_crossscorer.log\", \"submitted_at\": \"2026-05-18T02:44:54.483Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_arXiv_llama8b_crossscorer/\", \"data_count\": 6, \"model_name\": \"pythia-1.4b\", \"seed\": 42, \"checkpoint_source\": \"exp_arXiv_llama8b\", \"eval_data\": \"arXiv LLaMA-8B depth 0-5 continuations from exp_arXiv_llama8b\", \"checkpoint_path\": \"results/exp_arXiv_llama8b_crossscorer/\", \"wall_clock_seconds\": 1119.6, \"gpu_hours\": 0.31}, \"reproduce\": {\"finished_at\": \"2026-05-18T03:00:23.861Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T03:00:27.320630+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 3, \"auc_0v1\": 0.9629, \"auc_1v2\": 0.8433, \"auc_2v3\": 0.6201, \"auc_3v4\": 0.523, \"auc_4v5\": 0.5245, \"jsd_0v1\": 0.1214, \"jsd_1v2\": 0.0815, \"jsd_2v3\": 0.0195, \"jsd_3v4\": 0.0083, \"jsd_4v5\": 0.0082, \"ordinal_mae\": 0.9025, \"ordinal_accuracy\": 0.4407, \"scorer\": \"pythia-1.4b\"}, \"completed_at\": \"2026-05-18T03:03:34.051Z\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_llama8b_crossscorer.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_arXiv_llama8b_crossscorer/\"}, \"exp_arXiv_qwen7b_crossscorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T02:13:55.051Z\", \"updated_at\": \"2026-05-18T03:04:22.586Z\", \"hypothesis\": \"arXiv cross-scorer (7B): Pythia-1.4B scorer 重评 Qwen-7B arXiv depth 0-5。D060 Wiki scorer confound 推导。关键 2v3 AUC ≥0.60 → K*=3 scorer-independent。\", \"parent\": \"exp_wiki_scorer_confound\", \"spec\": {\"command\": \"run_pipeline.py --skip_generation\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"195291\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_qwen7b_crossscorer.log\", \"submitted_at\": \"2026-05-18T02:44:45.812Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/exp_arXiv_qwen7b_crossscorer\", \"data_count\": 2200, \"model_name\": \"Qwen/Qwen2.5-7B\", \"seed\": 42, \"checkpoint_source\": \"exp_arXiv_qwen7b\", \"eval_data\": \"arXiv Qwen-7B depth 0-5 from exp_arXiv_qwen7b\", \"wall_clock_seconds\": 1156.0, \"gpu_hours\": 0.32, \"checkpoint_path\": \"results/exp_arXiv_qwen7b_crossscorer/\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T02:59:40.126Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"negative\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:18:26.248465+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:59:43.427079+00:00\"}]}, \"notes\": \"Hypothesis rejected: cross-scorer 2v3 AUC=0.5989 < 0.60, K* drops from 3→2. Mild Qwen family bias (~0.027 AUC at 2v3) inflates original K*=3. Scorer-independent K*=2. Borderline: 3/5 folds above 0.60. Depths 0-2 robustly scorer-independent.\", \"metrics\": {\"k_star\": 2, \"auc_0v1\": 0.9575, \"auc_1v2\": 0.8171, \"auc_2v3\": 0.5989, \"auc_3v4\": 0.5417, \"auc_4v5\": 0.5192, \"jsd_0v1\": 0.137085, \"jsd_1v2\": 0.059688, \"jsd_2v3\": 0.013508, \"jsd_3v4\": 0.009125, \"jsd_4v5\": 0.006738, \"ordinal_mae\": 0.9617, \"ordinal_accuracy\": 0.4255}, \"checkpoint_path\": \"N/A (scoring-only experiment, no training checkpoint)\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_qwen7b_crossscorer.log\", \"completed_at\": \"2026-05-18T03:04:01.839Z\"}, \"exp_arXiv_qwen1b5_crossscorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T02:13:56.083Z\", \"updated_at\": \"2026-05-18T03:02:38.562Z\", \"hypothesis\": \"arXiv cross-scorer (1.5B): Pythia-1.4B scorer 重评 Qwen-1.5B arXiv depth 0-5。验证 K*=3 scorer-independent。\", \"parent\": \"exp_wiki_scorer_confound\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && mkdir -p data/exp_arXiv_qwen1b5_crossscorer && for d in 0 1 2 3 4 5; do ln -sf /root/autodl-tmp/gen-depth-contamination/data/exp_024_arxiv/depth_\\\\${d}.jsonl data/exp_arXiv_qwen1b5_crossscorer/depth_\\\\${d}.jsonl; done && mkdir -p results/exp_arXiv_qwen1b5_crossscorer && HF_HOME=/root/autodl-tmp/.hf_cache TRANSFORMERS_CACHE=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --scorer_path /root/autodl-tmp/.hf_cache/hub/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_arXiv_qwen1b5_crossscorer --results_dir results/exp_arXiv_qwen1b5_crossscorer --num_samples 2200 --max_depth 5 --batch_size 16 --generation_mode continuation --skip_generation\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"195826\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_qwen1b5_crossscorer.log\", \"submitted_at\": \"2026-05-18T02:44:53.081Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"results/exp_arXiv_qwen1b5_crossscorer/\", \"wall_clock_seconds\": 1065.5, \"gpu_hours\": 0.3}, \"reproduce\": {\"finished_at\": \"2026-05-18T02:59:46.327Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"success\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:18:40.560606+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:59:52.404331+00:00\"}]}, \"notes\": \"首次提交因 symlink 问题失败 (EXIT_CODE=1)，Worker 修复后重跑成功 (EXIT_CODE=0)。Pythia-1.4B scorer 重评 Qwen-1.5B arXiv 文本 K*=3，与 Qwen scorer 一致，确认 arXiv K*=3 scorer-independent。\", \"metrics\": {\"k_star\": 3, \"auc_0v1\": 0.9748, \"auc_1v2\": 0.8105, \"auc_2v3\": 0.6317, \"auc_3v4\": 0.5437, \"auc_4v5\": 0.5294, \"jsd_0v1\": 0.154297, \"jsd_1v2\": 0.066782, \"jsd_2v3\": 0.019268, \"jsd_3v4\": 0.008867, \"jsd_4v5\": 0.006991, \"ordinal_mae\": 0.9017, \"ordinal_accuracy\": 0.4402}, \"completed_at\": \"2026-05-18T03:02:38.562Z\"}, \"exp_wiki_scorer_confound_1b5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:18:37.565Z\", \"updated_at\": \"2026-05-18T01:21:43.381Z\", \"hypothesis\": \"Scorer family bias replication (Qwen-1.5B): 用 Pythia-1.4B 替代 Qwen-1.5B 作为 scorer 重新评分 exp_023_domain_ablation (Qwen-1.5B Wiki depth 0-5) 文本。如果 Pythia scorer 下 K* 仍=2 → confound excluded for both Qwen scales；如果 K*=1 → scorer confound confirmed，与 Qwen-7B 复验一致。\", \"parent\": \"exp_023_domain_ablation\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T23:20:01.037Z\", \"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && mkdir -p data/exp_wiki_scorer_confound_1b5 && for d in 0 1 2 3 4 5; do ln -sf /root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/depth_\\\\${d}.jsonl data/exp_wiki_scorer_confound_1b5/depth_\\\\${d}.jsonl; done && mkdir -p results/exp_wiki_scorer_confound_1b5 && HF_HOME=/root/autodl-tmp/.hf_cache TRANSFORMERS_CACHE=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --scorer_path /root/autodl-tmp/.hf_cache/hub/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_wiki_scorer_confound_1b5 --results_dir results/exp_wiki_scorer_confound_1b5 --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-18T01:18:40.529Z\", \"training_hours\": 1.98}, \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && mkdir -p data/exp_wiki_scorer_confound_1b5 && for d in 0 1 2 3 4 5; do ln -sf /root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/depth_\\\\${d}.jsonl data/exp_wiki_scorer_confound_1b5/depth_\\\\${d}.jsonl; done && mkdir -p results/exp_wiki_scorer_confound_1b5 && HF_HOME=/root/autodl-tmp/.hf_cache TRANSFORMERS_CACHE=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --scorer_path /root/autodl-tmp/.hf_cache/hub/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_wiki_scorer_confound_1b5 --results_dir results/exp_wiki_scorer_confound_1b5 --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"180543\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_scorer_confound_1b5.log\", \"submitted_at\": \"2026-05-17T23:22:42.473Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7140.9, \"gpu_hours\": 1.98}, \"pid\": \"180543\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_scorer_confound_1b5.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T01:18:44.039720+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"k_star\": 1, \"confound_verdict\": \"confirmed\", \"auc_0v1\": 0.9729, \"auc_1v2\": 0.5994, \"auc_2v3\": 0.533, \"auc_3v4\": 0.5214, \"auc_4v5\": 0.5068, \"jsd_0v1\": 0.0886, \"ordinal_mae\": 1.2995, \"ordinal_accuracy\": 0.3466}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_scorer_confound_1b5/\", \"completed_at\": \"2026-05-18T01:21:43.381Z\"}, \"exp_wiki_scorer_confound\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T22:35:20.326Z\", \"updated_at\": \"2026-05-17T23:20:31.517Z\", \"hypothesis\": \"Scorer family bias test: Qwen-7B Wikipedia K*=2 是 Qwen-1.5B scorer 的 family bias artifact 还是真实信号？用 Pythia-1.4B 替代 Qwen-1.5B 作为 scorer 重新评分同一批 depth 0-5 文本。如果 Pythia scorer 下 K* 仍=2 → confound excluded；如果 K*=1 → scorer confound confirmed。\", \"parent\": \"exp_wiki_qwen7b\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T22:55:01.348Z\", \"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && mkdir -p data/exp_wiki_scorer_confound && for d in 0 1 2 3 4 5; do ln -sf /root/autodl-tmp/gen-depth-contamination/data/exp_wiki_qwen7b/depth_\\\\${d}.jsonl data/exp_wiki_scorer_confound/depth_\\\\${d}.jsonl; done && mkdir -p results/exp_wiki_scorer_confound && HF_HOME=/root/autodl-tmp/.hf_cache TRANSFORMERS_CACHE=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --scorer_path /root/autodl-tmp/.hf_cache/hub/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_wiki_scorer_confound --results_dir results/exp_wiki_scorer_confound --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-17T23:13:55.501Z\", \"training_hours\": 0.32}, \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && mkdir -p data/exp_wiki_scorer_confound && for d in 0 1 2 3 4 5; do ln -sf /root/autodl-tmp/gen-depth-contamination/data/exp_wiki_qwen7b/depth_\\\\${d}.jsonl data/exp_wiki_scorer_confound/depth_\\\\${d}.jsonl; done && mkdir -p results/exp_wiki_scorer_confound && HF_HOME=/root/autodl-tmp/.hf_cache TRANSFORMERS_CACHE=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --scorer_path /root/autodl-tmp/.hf_cache/hub/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --data_dir data/exp_wiki_scorer_confound --results_dir results/exp_wiki_scorer_confound --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"178762\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_scorer_confound.log\", \"submitted_at\": \"2026-05-17T22:55:03.139Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_scorer_confound/\", \"wall_clock_seconds\": 1528.4, \"gpu_hours\": 0.42}, \"pid\": \"178762\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_scorer_confound.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T23:13:58.836236+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"k_star\": 1, \"confound_verdict\": \"confirmed\", \"auc_0v1\": 0.9404, \"auc_1v2\": 0.587, \"auc_2v3\": 0.5456, \"auc_3v4\": 0.525, \"auc_4v5\": 0.5172, \"critical_delta_1v2\": -0.0238}, \"completed_at\": \"2026-05-17T23:20:31.517Z\"}, \"exp_wiki_qwen7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T16:39:29.006Z\", \"updated_at\": \"2026-05-17T22:24:51.126Z\", \"hypothesis\": \"Cross-scale Wikipedia K* validation: Qwen2.5-7B continuation on Wikipedia 的 K* 是否 = 2？Qwen2.5-1.5B 在 Wikipedia K*=2（唯一维持 K*=2 的模型），Pythia/OLMo/均 K*=1。测试 7B 规模是否仍维持 Qwen 家族在 Wikipedia 上的 K*=2 pattern。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_arXiv_qwen7b\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T17:02:41.963Z\", \"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --data_dir data/exp_wiki_qwen7b --results_dir results/exp_wiki_qwen7b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-17T22:21:53.554Z\", \"training_hours\": 5.32}, \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --data_dir data/exp_wiki_qwen7b --results_dir results/exp_wiki_qwen7b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"732600\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_qwen7b.log\", \"submitted_at\": \"2026-05-17T17:02:43.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 19327.6, \"gpu_hours\": 5.37}, \"pid\": \"732600\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_qwen7b.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T22:21:56.559363+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"K_star\": 2, \"auc_0v1\": 0.9673, \"auc_1v2\": 0.6108, \"auc_2v3\": 0.5562, \"auc_3v4\": 0.5297, \"auc_4v5\": 0.529, \"jsd_0v1\": 0.083514, \"jsd_1v2\": 0.010991, \"jsd_2v3\": 0.00555, \"jsd_3v4\": 0.004611, \"jsd_4v5\": 0.003894, \"ordinal_mae\": 1.2501, \"ordinal_accuracy\": 0.3532}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_qwen7b\", \"completed_at\": \"2026-05-17T22:24:51.126Z\"}, \"exp_wiki_mistral7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:04:15.959Z\", \"updated_at\": \"2026-05-17T19:53:56.272Z\", \"hypothesis\": \"Mistral-7B Wikipedia K* test: Mistral-7B-v0.3 在 C4 上 K*=1 (text-intrinsic one-wash)。在 Wikipedia domain 上是否仍 K*=1？Pythia/OLMo 在 Wikipedia 均 K*=1，Qwen K*=2。如果 Mistral K*=1 → 确认 one-wash 跨域成立；如果 K*>1 → Wikipedia 有 rescue Mistral 的结构信号（与预期相反）。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_wiki_pythia_v2\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T14:05:42.553Z\", \"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/mistralai/Mistral-7B-v0___3 --data_dir data/exp_wiki_mistral7b --results_dir results/exp_wiki_mistral7b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-17T19:50:28.711Z\", \"training_hours\": 5.75}, \"spec\": {\"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/mistralai/Mistral-7B-v0___3 --data_dir data/exp_wiki_mistral7b --results_dir results/exp_wiki_mistral7b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"data_path\": \"data/exp_wiki_mistral7b\", \"data_count\": 5000, \"model_name\": \"mistralai/Mistral-7B-v0.3\", \"seed\": 42, \"checkpoint_source\": \"pretrained:mistralai/Mistral-7B-v0.3\", \"eval_data\": \"Wikipedia depth 0-5, scorer=Qwen2.5-1.5B\"}, \"pid\": \"41845\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_mistral7b.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T19:50:32.601540+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_mistral7b\", \"metrics\": {\"K_star\": 1, \"ordinal_mae\": 1.3445, \"ordinal_accuracy\": 0.3273, \"auc_0v1\": 0.9607, \"auc_1v2\": 0.5552, \"auc_2v3\": 0.5236, \"auc_3v4\": 0.5181, \"auc_4v5\": 0.5012, \"jsd_0v1\": 0.054134, \"jsd_1v2\": 0.005678, \"jsd_2v3\": 0.003698, \"jsd_3v4\": 0.003459, \"jsd_4v5\": 0.003274}, \"completed_at\": \"2026-05-17T19:53:56.272Z\"}, \"exp_wiki_llama8b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:27:37.043Z\", \"updated_at\": \"2026-05-17T19:33:39.300Z\", \"hypothesis\": \"Cross-scale Wikipedia K* validation: LLaMA-3.1-8B continuation on Wikipedia 的 K* 是否 = 2？Pythia-1.4B K*=1, Qwen-1.5B K*=2, OLMo-1B K*=1。测试 8B scale 是否能在 Wikipedia 均质 domain 上维持 K*=2（scale 是否是决定因素）。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_wiki_pythia_v2\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-17T13:29:58.320Z\", \"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/LLM-Research/Meta-Llama-3___1-8B --data_dir data/exp_wiki_llama8b --results_dir results/exp_wiki_llama8b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-17T19:30:35.869Z\", \"training_hours\": 6.01}, \"spec\": {\"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/LLM-Research/Meta-Llama-3___1-8B --data_dir data/exp_wiki_llama8b --results_dir results/exp_wiki_llama8b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"data_path\": \"data/exp_wiki_llama8b\", \"data_count\": 5000, \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"pretrained:LLM-Research/Meta-Llama-3.1-8B\", \"eval_data\": \"Wikipedia depth 0-5, scorer=Qwen2.5-1.5B\"}, \"pid\": \"38142\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_llama8b.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T19:30:39.064445+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"K_star\": 1, \"ordinal_mae\": 1.2954, \"ordinal_accuracy\": 0.3313, \"auc_0v1\": 0.9316, \"auc_1v2\": 0.5954, \"auc_2v3\": 0.5392, \"auc_3v4\": 0.5221, \"auc_4v5\": 0.5212, \"jsd_0v1\": 0.06169, \"jsd_1v2\": 0.00931}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_llama8b\", \"completed_at\": \"2026-05-17T19:33:39.300Z\"}, \"exp_arXiv_qwen7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T12:56:03.934Z\", \"updated_at\": \"2026-05-17T16:36:58.029Z\", \"hypothesis\": \"Qwen2.5-7B on arXiv abstracts will yield K*=3, validating that structured domain K*=3 is stable within the Qwen family across scales (1.5B vs 7B)\", \"parent\": \"exp_024_arxiv_domain\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T14:08:40.926Z\", \"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --data_dir data/exp_arXiv_qwen7b --results_dir results/exp_arXiv_qwen7b --num_samples 2200 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-17T16:34:23.946Z\", \"training_hours\": 2.43}, \"spec\": {\"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-7B --data_dir data/exp_arXiv_qwen7b --results_dir results/exp_arXiv_qwen7b --num_samples 2200 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/exp_arXiv_qwen7b\", \"data_count\": 2200, \"model_name\": \"Qwen2.5-7B\", \"seed\": 42, \"checkpoint_source\": \"pretrained:Qwen/Qwen2.5-7B\", \"eval_data\": \"arXiv abstracts depth 0-5, scorer=Qwen2.5-1.5B\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_arXiv_qwen7b\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_qwen7b.log\"}, \"pid\": \"42742\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_qwen7b.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T16:34:26.949400+00:00\"}]}, \"metrics\": {\"k_star\": 3, \"pairwise_auc\": {\"0v1\": 0.983, \"1v2\": 0.835, \"2v3\": 0.626, \"3v4\": 0.544, \"4v5\": 0.513}, \"pairwise_jsd\": {\"0v1\": 0.1656, \"1v2\": 0.0668, \"2v3\": 0.0156, \"3v4\": 0.0089, \"4v5\": 0.0061}, \"ordinal_mae\": 0.9, \"ordinal_accuracy\": 0.446}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T16:36:58.029Z\"}, \"exp_arXiv_mistral7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:32:28.299Z\", \"updated_at\": \"2026-05-17T16:28:24.294Z\", \"hypothesis\": \"Mistral-7B arXiv K* test: Mistral-7B-v0.3 在 C4 上 K*=1 (one-wash model)。在 arXiv structured domain 上是否仍 K*=1？如果 K*=1 → 确认 Mistral 的 one-wash 是 text-intrinsic (与 domain 无关)；如果 K*>1 → domain complexity 可以 rescue one-wash models，K* 同时受 model 和 domain 驱动。2200 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_arXiv_olmo\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-17T13:53:18.456Z\", \"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/mistralai/Mistral-7B-v0___3 --data_dir data/exp_arXiv_mistral7b --results_dir results/exp_arXiv_mistral7b --num_samples 2200 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"code_commit\": \"0b10b4309bd03e7fcc3cbeb7fca54744d69a73b5\", \"finished_at\": \"2026-05-17T16:25:00.229Z\", \"training_hours\": 2.53}, \"spec\": {\"command\": \"cd /root/autodl-tmp/gen-depth-contamination && /root/miniconda3/bin/python3.12 scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/mistralai/Mistral-7B-v0___3 --data_dir data/exp_arXiv_mistral7b --results_dir results/exp_arXiv_mistral7b --num_samples 2200 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"data_path\": \"data/exp_arXiv_mistral7b\", \"data_count\": 2200, \"model_name\": \"mistralai/Mistral-7B-v0.3\", \"seed\": 42, \"checkpoint_source\": \"pretrained:mistralai/Mistral-7B-v0.3\", \"eval_data\": \"arXiv abstracts depth 0-5, scorer=Qwen2.5-1.5B\"}, \"pid\": \"40472\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_mistral7b.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T16:25:03.226062+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 3, \"pairwise_auc\": {\"0v1\": 0.9848, \"1v2\": 0.8201, \"2v3\": 0.6275, \"3v4\": 0.5295, \"4v5\": 0.5295}, \"jsd\": {\"0v1\": 0.14249, \"1v2\": 0.076232, \"2v3\": 0.018972, \"3v4\": 0.009908, \"4v5\": 0.008877}, \"ordinal_mae\": 0.8958, \"ordinal_accuracy\": 0.4474, \"top_features\": [\"freq_entropy\", \"surp_std\", \"surp_d1_skew\", \"surp_mean\", \"surp_d2_mean\"]}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_arXiv_mistral7b\", \"completed_at\": \"2026-05-17T16:28:24.294Z\"}, \"exp_arXiv_llama8b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:53:57.754Z\", \"updated_at\": \"2026-05-17T14:02:45.388Z\", \"hypothesis\": \"Cross-architecture arXiv K* validation: LLaMA-3.1-8B continuation on arXiv abstracts 的 K* 是否 = 3？验证 structured domain K*=3 在大模型（8B scale）上是否成立，排除小模型 capacity artifact。2200 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_024_arxiv_domain\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T10:59:48.493Z\", \"finished_at\": \"2026-05-17T13:59:25.526Z\", \"training_hours\": 2.99}, \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/LLM-Research/Meta-Llama-3___1-8B --data_dir data/exp_arXiv_llama8b --results_dir results/exp_arXiv_llama8b --num_samples 2200 --max_depth 5 --batch_size 8 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"27469\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_llama8b.log\", \"submitted_at\": \"2026-05-17T11:23:08.013Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/exp_arXiv_llama8b (seed from exp_024_arxiv/depth_0.jsonl)\", \"data_count\": 2200, \"model_name\": \"Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"pretrained:LLM-Research/Meta-Llama-3.1-8B\", \"eval_data\": \"arXiv abstracts depth 0-5, scorer=Qwen2.5-1.5B\", \"wall_clock_seconds\": 9577.4, \"gpu_hours\": 2.66}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:59:27.415949+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"K_star\": 3, \"auc_0v1\": 0.9754, \"auc_1v2\": 0.8447, \"auc_2v3\": 0.6215, \"auc_3v4\": 0.5362, \"auc_4v5\": 0.5331, \"jsd_0v1\": 0.1296, \"jsd_1v2\": 0.0785, \"jsd_2v3\": 0.0177, \"ordinal_acc\": 0.4549, \"ordinal_mae\": 0.8806}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_arXiv_llama8b/\", \"completed_at\": \"2026-05-17T14:02:45.388Z\"}, \"exp_wiki_pythia_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:40:37.896Z\", \"updated_at\": \"2026-05-17T13:25:22.734Z\", \"hypothesis\": \"Cross-model Wikipedia K* validation (v2 fix): Pythia-1.4B continuation on Wikipedia 的 K* 是否 = 2？使用独立 data_dir 避免 v1 的 data reuse bug，让 pipeline 用 Pythia 重新生成 depth 1-5。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_wiki_pythia\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path ...pythia-1.4b... --generation_mode continuation\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"30942\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_pythia_v2.log\", \"submitted_at\": \"2026-05-17T11:48:32.895Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/exp_wiki_pythia\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b\", \"seed\": 42, \"git_commit\": \"0b10b43\", \"checkpoint_source\": \"N/A (generation experiment, not eval)\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 5809.8, \"gpu_hours\": 1.61}, \"reproduce\": {\"finished_at\": \"2026-05-17T13:15:30.480Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:15:32.903668+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"K_star\": 1, \"auc_0v1\": 0.975, \"auc_1v2\": 0.5846, \"auc_2v3\": 0.5445, \"auc_3v4\": 0.5205, \"auc_4v5\": 0.5168, \"jsd_0v1\": 0.080065, \"jsd_1v2\": 0.007773, \"ordinal_acc\": 0.3503}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_pythia_v2/\", \"completed_at\": \"2026-05-17T13:25:22.734Z\"}, \"exp_wiki_olmo_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:40:38.784Z\", \"updated_at\": \"2026-05-17T13:23:57.369Z\", \"hypothesis\": \"Cross-model Wikipedia K* validation (v2 fix): OLMo-1B continuation on Wikipedia 的 K* 是否 = 2？使用独立 data_dir 避免 v1 的 data reuse bug，让 pipeline 用 OLMo 重新生成 depth 1-5。5000 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_wiki_olmo\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path .../allenai/OLMo-1B-hf --generation_mode continuation\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"31084\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_olmo_v2.log\", \"submitted_at\": \"2026-05-17T11:48:36.028Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/exp_wiki_olmo\", \"data_count\": 5000, \"model_name\": \"allenai/OLMo-1B-hf\", \"seed\": 42, \"git_commit\": \"0b10b43\", \"checkpoint_source\": \"N/A (generation experiment, not eval)\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 5721.3, \"gpu_hours\": 1.59}, \"reproduce\": {\"finished_at\": \"2026-05-17T13:08:49.908Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:08:52.662189+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"K_star\": 1, \"auc_0v1\": 0.9932, \"auc_1v2\": 0.4986, \"auc_2v3\": 0.5012, \"auc_3v4\": 0.5057, \"auc_4v5\": 0.5009, \"jsd_0v1\": 0.1688, \"ordinal_acc\": 0.3227}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_wiki_olmo_v2/\", \"completed_at\": \"2026-05-17T13:23:57.369Z\"}, \"exp_arXiv_olmo\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:53:55.374Z\", \"updated_at\": \"2026-05-17T12:28:50.616Z\", \"hypothesis\": \"Cross-model arXiv K* validation: OLMo-1B continuation on arXiv abstracts 的 K* 是否 = 3（与 exp-024 Qwen 和 exp-025 Pythia 一致）？验证 structured domain K*=3 跨第三个模型架构（OLMo）的稳定性。2200 docs, depth 0-5, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_024_arxiv_domain\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T10:59:47.281Z\", \"finished_at\": \"2026-05-17T12:11:06.144Z\", \"training_hours\": 1.19}, \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/allenai/OLMo-1B-hf --data_dir data/exp_arXiv_olmo --results_dir results/exp_arXiv_olmo --num_samples 2200 --max_depth 5 --batch_size 16 --generation_mode continuation --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"26733\", \"log_path\": \"~/runs/gen-depth-contamination/exp_arXiv_olmo.log\", \"submitted_at\": \"2026-05-17T11:23:00.352Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/exp_arXiv_olmo (seed from exp_024_arxiv/depth_0.jsonl)\", \"data_count\": 2200, \"model_name\": \"OLMo-1B-hf\", \"seed\": 42, \"checkpoint_source\": \"pretrained:allenai/OLMo-1B-hf\", \"eval_data\": \"arXiv abstracts depth 0-5, scorer=Qwen2.5-1.5B\", \"wall_clock_seconds\": 3950.3, \"gpu_hours\": 1.1}, \"conclusion\": \"negative\", \"metrics\": {\"K_star\": 1, \"auc_0v1\": 0.9958, \"auc_1v2\": 0.5034, \"auc_2v3\": 0.5069, \"auc_3v4\": 0.5021, \"auc_4v5\": 0.5037, \"jsd_0v1\": 0.329, \"ordinal_acc\": 0.33}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_arXiv_olmo/\", \"completed_at\": \"2026-05-17T12:28:50.616Z\"}, \"exp_wiki_olmo\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:54:01.835Z\", \"updated_at\": \"2026-05-17T11:40:31.501Z\", \"hypothesis\": \"OLMo-1B continuation on Wikipedia domain will show K*=2 depth saturation pattern consistent with Qwen2.5-1.5B, demonstrating cross-model generality of the distinguishability decay phenomenon.\", \"parent\": \"exp_023_domain_ablation\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-17T10:59:50.182Z\"}, \"spec\": {\"command\": \"python scripts/run_pipeline.py ...\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"27620\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_olmo.log\", \"submitted_at\": \"2026-05-17T11:23:10.688Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/\", \"data_count\": 5000, \"model_name\": \"allenai/OLMo-1B-hf\", \"seed\": 42, \"git_commit\": \"N/A\", \"checkpoint_source\": \"/root/autodl-tmp/.hf_cache/allenai/OLMo-1B-hf\", \"eval_data\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/\", \"wall_clock_seconds\": 1040.8, \"gpu_hours\": 0.29}, \"conclusion\": \"failed\", \"notes\": \"INVALID: data reuse bug. Shared data_path /root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/ with exp-023 (Qwen). Pipeline skip-if-exists logic reused Qwen-generated depth files instead of generating with OLMo. Results identical to exp-023. M002 lesson: each experiment must use independent data directory.\", \"checkpoint_path\": \"N/A (invalid run)\", \"log_path\": \"/root/runs/gen-depth-contamination/exp_wiki_olmo.log\", \"completed_at\": \"2026-05-17T11:40:31.501Z\"}, \"exp_wiki_pythia\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:54:00.154Z\", \"updated_at\": \"2026-05-17T11:40:30.671Z\", \"hypothesis\": \"Pythia-1.4B continuation on Wikipedia domain will show K*=2 depth saturation pattern consistent with Qwen2.5-1.5B, demonstrating cross-model generality of the distinguishability decay phenomenon.\", \"parent\": \"exp_023_domain_ablation\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-17T10:59:49.483Z\"}, \"spec\": {\"command\": \"python scripts/run_pipeline.py ...\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"26873\", \"log_path\": \"~/runs/gen-depth-contamination/exp_wiki_pythia.log\", \"submitted_at\": \"2026-05-17T11:23:03.344Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b\", \"seed\": 42, \"git_commit\": \"N/A\", \"checkpoint_source\": \"/root/autodl-tmp/.hf_cache/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79\", \"eval_data\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/\", \"wall_clock_seconds\": 1047.3, \"gpu_hours\": 0.29}, \"conclusion\": \"failed\", \"notes\": \"INVALID: data reuse bug. Shared data_path /root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/ with exp-023 (Qwen). Pipeline skip-if-exists logic reused Qwen-generated depth files instead of generating with Pythia. Results identical to exp-023 (1v2=0.6193, K*=2). M002 lesson: each experiment must use independent data directory.\", \"checkpoint_path\": \"N/A (invalid run)\", \"log_path\": \"/root/runs/gen-depth-contamination/exp_wiki_pythia.log\", \"completed_at\": \"2026-05-17T11:40:30.671Z\"}, \"exp_009_dose_response\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T22:17:38.441Z\", \"updated_at\": \"2026-05-17T10:24:24.214Z\", \"hypothesis\": \"Contamination dose-response: 在 10%/30%/50% synthetic injection 比例下，graduated filtering 相对 binary filtering 的收益是否随 contamination 增加而扩大？验证 C3 (graduated filtering superiority) 在不同 contamination severity 下的 robustness。3 ratios × 3 strategies (no-filter/binary/graduated) × 5 seeds, continued pretraining Qwen2.5-1.5B, eval MMLU+HellaSwag.\", \"spec\": {\"command\": \"exp009_dose_response.py --ratio {0.1,0.3,0.5}\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B\", \"seed\": \"0-4\", \"checkpoint_source\": \"N/A (continued pretraining from base)\", \"eval_data\": \"MMLU + HellaSwag (lm-eval-harness)\"}, \"metrics\": {\"total_runs\": 45, \"seeds\": 5, \"ratios\": [0.1, 0.3, 0.5], \"strategies\": [\"no_filter\", \"binary_ours\", \"graduated\"], \"cross_ratio_finding\": \"Binary filtering consistently best across all ratios. Graduated filtering = no_filter at every ratio. Effect size of binary advantage increases with contamination ratio (HellaSwag delta: 10%=+0.38pp, 30%=+0.61pp, 50%=+0.51pp). Original C3 hypothesis (graduated > binary) rejected.\", \"gpu_hours_total\": 9.9}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_009_dose_response/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp009_v3_partial_10_30.json\", \"completed_at\": \"2026-05-17T10:24:24.214Z\"}, \"exp_009_dose_50pct_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T00:13:08.251Z\", \"updated_at\": \"2026-05-17T10:23:52.356Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && export HF_DATASETS_OFFLINE=1 && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && python scripts/exp009_dose_response.py --ratio 0.5 --device cuda:0 --num_seeds 5\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"4404\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_50pct_v3.log\", \"submitted_at\": \"2026-05-17T07:05:48.783Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11883.6, \"gpu_hours\": 3.3}, \"hypothesis\": \"50% synthetic injection 下 graduated filtering 应展现最大优势 >=2pp MMLU（v3: fix OOM, auto batch + offline）。半数数据为合成时 binary 激进丢弃导致数据饥饿。\", \"parent\": \"exp_009_dose_50pct_v2\", \"metrics\": {\"seeds\": 5, \"strategies\": 3, \"total_runs\": 15, \"mean_std\": {\"no_filter\": {\"mmlu\": \"0.6063±0.0013\", \"hellaswag\": \"0.6680±0.0005\"}, \"binary_ours\": {\"mmlu\": \"0.6088±0.0011\", \"hellaswag\": \"0.6731±0.0004\"}, \"graduated\": {\"mmlu\": \"0.6062±0.0009\", \"hellaswag\": \"0.6679±0.0002\"}}, \"paired_ttest\": {\"binary_vs_nofilter\": {\"delta_mmlu\": 0.0025, \"p_mmlu\": 0.0377, \"delta_hellaswag\": 0.0051, \"p_hellaswag\": 2e-05}, \"graduated_vs_binary\": {\"delta_mmlu\": -0.0026, \"p_mmlu\": 0.0257, \"delta_hellaswag\": -0.0052, \"p_hellaswag\": 3e-05}, \"graduated_vs_nofilter\": {\"delta_mmlu\": -0.0001, \"p_mmlu\": 0.89, \"delta_hellaswag\": -0.0001, \"p_hellaswag\": 0.706}}, \"key_finding\": \"Binary significantly best (HellaSwag p<0.001). Graduated = no_filter exactly.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_009_dose_response/ratio_50/\", \"completed_at\": \"2026-05-17T10:23:52.356Z\"}, \"exp_009_dose_30pct_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T00:13:06.603Z\", \"updated_at\": \"2026-05-17T10:23:51.631Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && export HF_DATASETS_OFFLINE=1 && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && python scripts/exp009_dose_response.py --ratio 0.3 --device cuda:0 --num_seeds 5\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"4327\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_30pct_v3.log\", \"submitted_at\": \"2026-05-17T07:05:47.584Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11884.0, \"gpu_hours\": 3.3}, \"hypothesis\": \"30% synthetic injection 下 graduated filtering 优势应 >=1pp MMLU（v3: fix OOM, auto batch + offline）。更高污染率下 binary 丢弃更多可用 gen-1 数据。\", \"parent\": \"exp_009_dose_30pct_v2\", \"metrics\": {\"seeds\": 5, \"strategies\": 3, \"total_runs\": 15, \"mean_std\": {\"no_filter\": {\"mmlu\": \"0.6069±0.0007\", \"hellaswag\": \"0.6664±0.0020\"}, \"binary_ours\": {\"mmlu\": \"0.6082±0.0012\", \"hellaswag\": \"0.6725±0.0007\"}, \"graduated\": {\"mmlu\": \"0.6072±0.0008\", \"hellaswag\": \"0.6665±0.0014\"}}, \"paired_ttest\": {\"binary_vs_nofilter\": {\"delta_mmlu\": 0.0013, \"p_mmlu\": 0.0739, \"delta_hellaswag\": 0.0061, \"p_hellaswag\": 0.0036}, \"graduated_vs_binary\": {\"delta_mmlu\": -0.001, \"p_mmlu\": 0.3018, \"delta_hellaswag\": -0.006, \"p_hellaswag\": 0.0009}, \"graduated_vs_nofilter\": {\"delta_mmlu\": 0.0003, \"p_mmlu\": 0.6638, \"delta_hellaswag\": 0.0002, \"p_hellaswag\": 0.6646}}, \"key_finding\": \"Binary best on HellaSwag (p=0.004). Graduated = no_filter.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_009_dose_response/ratio_30/\", \"completed_at\": \"2026-05-17T10:23:51.631Z\"}, \"exp_009_dose_10pct_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T00:13:04.692Z\", \"updated_at\": \"2026-05-17T10:23:50.749Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && export HF_DATASETS_OFFLINE=1 && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && python scripts/exp009_dose_response.py --ratio 0.1 --device cuda:0 --num_seeds 5\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"4187\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_10pct_v3.log\", \"submitted_at\": \"2026-05-17T07:05:45.840Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11884.9, \"gpu_hours\": 3.3}, \"hypothesis\": \"10% synthetic injection 下 graduated filtering 应比 binary 保留 >=0.5pp MMLU（v3: fix OOM, auto batch + offline）。低污染时 gen-1 有训练价值，binary 全丢造成数据损失。\", \"parent\": \"exp_009_dose_10pct_v2\", \"metrics\": {\"seeds\": 5, \"strategies\": 3, \"total_runs\": 15, \"mean_std\": {\"no_filter\": {\"mmlu\": \"0.6058±0.0002\", \"hellaswag\": \"0.6689±0.0007\"}, \"binary_ours\": {\"mmlu\": \"0.6079±0.0005\", \"hellaswag\": \"0.6727±0.0008\"}, \"graduated\": {\"mmlu\": \"0.6066±0.0011\", \"hellaswag\": \"0.6700±0.0015\"}}, \"paired_ttest\": {\"binary_vs_nofilter\": {\"delta_mmlu\": 0.0021, \"p_mmlu\": 0.001, \"delta_hellaswag\": 0.0038, \"p_hellaswag\": 0.0017}, \"graduated_vs_binary\": {\"delta_mmlu\": -0.0014, \"p_mmlu\": 0.0917, \"delta_hellaswag\": -0.0027, \"p_hellaswag\": 0.0399}, \"graduated_vs_nofilter\": {\"delta_mmlu\": 0.0008, \"p_mmlu\": 0.2706, \"delta_hellaswag\": 0.0011, \"p_hellaswag\": 0.0611}}, \"key_finding\": \"Binary best. Graduated ≈ no_filter.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_009_dose_response/ratio_10/\", \"completed_at\": \"2026-05-17T10:23:50.749Z\"}, \"exp_027_retrain_bootstrap\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:43:03.273Z\", \"updated_at\": \"2026-05-17T08:18:53.724Z\", \"hypothesis\": \"Retrain-chain 的 pairwise AUC（0v1 到 3v4）在 10000-iteration bootstrap 95% CI 下均显著高于 θ=0.60，确认 K*≥4 具有统计严格性。\", \"parent\": \"exp_008_retrain_chain_v2\", \"spec\": {\"command\": \"python scripts/exp027_retrain_bootstrap.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/features/exp_008_retrain_chain_v2_features.csv\", \"data_count\": 5000, \"model_name\": \"LightGBM (bootstrap analysis)\", \"seed\": 42, \"checkpoint_source\": \"exp_008_retrain_chain_v2 (retrain-chain AUC data)\", \"eval_data\": \"exp_008_retrain_chain_v2 pairwise depth features (0v1, 1v2, 2v3, 3v4)\"}, \"metrics\": {\"bootstrap_iterations\": 10000, \"pairs\": {\"0v1\": {\"auc_point\": 0.9847, \"ci_lower\": 0.9828, \"ci_upper\": 0.9864, \"perm_p\": 0.0001, \"ci_lower_gt_theta\": true}, \"1v2\": {\"auc_point\": 0.9482, \"ci_lower\": 0.9443, \"ci_upper\": 0.952, \"perm_p\": 0.0001, \"ci_lower_gt_theta\": true}, \"2v3\": {\"auc_point\": 0.8885, \"ci_lower\": 0.8829, \"ci_upper\": 0.894, \"perm_p\": 0.0001, \"ci_lower_gt_theta\": true}, \"3v4\": {\"auc_point\": 0.7977, \"ci_lower\": 0.7903, \"ci_upper\": 0.8051, \"perm_p\": 0.0001, \"ci_lower_gt_theta\": true}}, \"key_finding\": \"All 4 retrain-chain pairwise AUCs have CI_lower >> theta=0.60 (min CI_lower=0.7903). K*>=4 statistically confirmed with p<0.001.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp027_retrain_bootstrap.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp027_retrain_bootstrap.txt\", \"completed_at\": \"2026-05-17T08:18:53.724Z\"}, \"exp_026_feature_stability_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:09:57.776Z\", \"updated_at\": \"2026-05-17T08:15:28.177Z\", \"hypothesis\": \"Prompt-chain K*=2 边界对 feature 子集选择 robust：即使从 15D 中随机抽取 5/8/10 维子集，Pythia-1.4B prompt-chain 1v2 AUC（baseline ~0.654）仍 > θ=0.60，证明 K*=2 不依赖特定特征组合。\", \"parent\": \"exp_026_feature_stability\", \"metrics\": {\"data_source\": \"exp_001_pythia prompt-chain (K*=2)\", \"results\": {\"15D\": {\"num_tested\": 1, \"num_pass\": 1, \"min_1v2_auc\": 0.6262, \"mean_1v2_auc\": 0.6262}, \"10D\": {\"num_tested\": 5, \"num_pass\": 5, \"min_1v2_auc\": 0.6153, \"mean_1v2_auc\": 0.6191}, \"8D\": {\"num_tested\": 5, \"num_pass\": 5, \"min_1v2_auc\": 0.6056, \"mean_1v2_auc\": 0.6159}, \"5D\": {\"num_tested\": 5, \"num_pass\": 2, \"min_1v2_auc\": 0.5856, \"mean_1v2_auc\": 0.5998}, \"3D_top3\": {\"num_tested\": 1, \"num_pass\": 0, \"min_1v2_auc\": 0.5871, \"mean_1v2_auc\": 0.5871}}, \"key_finding\": \"8+ features sufficient for robust K*=2 (all pass θ=0.60). 5D fragile (2/5 pass). Top-3 alone fails. Feature diversity matters at the K* boundary.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp026_feature_stability_v2.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp026_feature_stability_v2.json\", \"spec\": {\"command\": \"python scripts/exp026_feature_stability.py --data_source exp_001_pythia\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/features/exp_001_pythia_features.csv\", \"data_count\": 5000, \"model_name\": \"LightGBM\", \"seed\": 42, \"checkpoint_source\": \"exp_001_pythia_depth (prompt-chain features)\", \"eval_data\": \"exp_001_pythia prompt-chain 1v2 features (15D statistical features)\"}, \"completed_at\": \"2026-05-17T08:15:28.177Z\"}, \"exp_026_feature_stability\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:43:01.256Z\", \"updated_at\": \"2026-05-17T08:10:04.334Z\", \"hypothesis\": \"K*=2 对 feature 子集选择 robust：即使从 15D 特征中随机抽取 5/8/10 维子集，1v2 AUC 仍 > θ=0.60，证明 K* 边界不依赖特定特征组合（ad-hoc feature 防御）。\", \"parent\": \"exp_B_14d_ablation\", \"metrics\": {\"data_source\": \"exp_016_qwen_base (prompt-chain, K*=2)\", \"results\": {\"15D\": {\"num_tested\": 1, \"num_kstar_2\": 1, \"min_1v2_auc\": 0.6262, \"mean_1v2_auc\": 0.6262}, \"10D\": {\"num_tested\": 5, \"num_kstar_2\": 5, \"min_1v2_auc\": 0.6153, \"mean_1v2_auc\": 0.6191}, \"8D\": {\"num_tested\": 5, \"num_kstar_2\": 5, \"min_1v2_auc\": 0.6056, \"mean_1v2_auc\": 0.6159}, \"5D\": {\"num_tested\": 5, \"num_kstar_2\": 2, \"min_1v2_auc\": 0.5856, \"mean_1v2_auc\": 0.5998}, \"3D_top3\": {\"num_tested\": 1, \"num_kstar_2\": 0, \"min_1v2_auc\": 0.5871, \"mean_1v2_auc\": 0.5871}}, \"all_above_theta\": false, \"key_finding\": \"Feature selection MATTERS at K*=2 boundary. 15D/10D/8D all robust (min 1v2 AUC > 0.60). 5D random subsets: only 2/5 pass θ=0.60 (min=0.5856). Top-3 features alone (0.5871) fail θ. Contrast with retrain-chain (K*=4) where all subsets trivially passed (min=0.8314).\", \"previous_run_note\": \"v1 used retrain-chain data (K*=4), where all subsets trivially passed with min 1v2 AUC=0.8314. v2 uses prompt-chain data (K*=2) to test boundary robustness.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp026_feature_stability.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp026_feature_stability.json\", \"spec\": {\"command\": \"python scripts/exp026_feature_stability.py\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_008_retrain_chain/\", \"data_count\": 5000, \"model_name\": \"LightGBM (feature subset ablation)\", \"seed\": 42, \"checkpoint_source\": \"exp_008_retrain_chain scored features\", \"eval_data\": \"retrain-chain 15D features depth 0-4\"}, \"completed_at\": \"2026-05-17T08:06:40.583Z\"}, \"exp_027\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:09:21.384Z\", \"updated_at\": \"2026-05-17T08:10:03.298Z\", \"hypothesis\": \"Document-level bootstrap CI (10000 iterations) on exp-008 v2 retrain-chain data will confirm that all 4 pairwise AUCs have CI_lower > theta=0.60, supporting K*>=4 with statistical significance.\", \"conclusion\": \"success\", \"checkpoint_path\": \"n/a\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp027.log\", \"completed_at\": \"2026-05-17T08:09:54.196Z\", \"metrics\": {\"kstar_ci\": 4, \"0v1_auc\": 0.9847, \"0v1_ci\": [0.9828, 0.9864], \"0v1_perm_p\": 0.0001, \"1v2_auc\": 0.9482, \"1v2_ci\": [0.9443, 0.952], \"1v2_perm_p\": 0.0001, \"2v3_auc\": 0.8885, \"2v3_ci\": [0.8829, 0.894], \"2v3_perm_p\": 0.0001, \"3v4_auc\": 0.7977, \"3v4_ci\": [0.7903, 0.8051], \"3v4_perm_p\": 0.0001, \"all_ci_lower_above_theta\": true}}, \"exp_005_degradation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T02:40:12.117Z\", \"updated_at\": \"2026-05-17T02:57:38.303Z\", \"spec\": {\"command\": \"python scripts/run_exp005_degradation.py --data_dirs results_exp001_pythia results_exp002_olmo data --labels Pythia-1.4B OLMo-1B Qwen-1.5B --output_dir results_exp005_degradation\", \"server\": \"autodl-4090d\", \"script_path\": \"/root/autodl-tmp/gen-depth-contamination/scripts/run_exp005_degradation.py\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp005_degradation\", \"data_count\": 15000, \"model_name\": \"Pythia-1.4B / OLMo-1B / Qwen-1.5B (3-model comparison)\", \"seed\": 42, \"input_dirs\": [\"results_exp001_pythia\", \"results_exp002_olmo\", \"data\"], \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp005_degradation/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_005_degradation.log\"}, \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp005_degradation/degradation_analysis.json\", \"metrics\": {\"cross_model_kendall_tau_by_first_auc\": {\"Pythia_vs_OLMo\": 0.733, \"Pythia_vs_Qwen_rewrite\": 0.467, \"Pythia_vs_Qwen_cont\": 0.695, \"OLMo_vs_Qwen_rewrite\": 0.429, \"OLMo_vs_Qwen_cont\": 0.543, \"Qwen_rewrite_vs_Qwen_cont\": 0.733}, \"cross_model_kendall_tau_by_avg_auc\": {\"Pythia_vs_OLMo\": 0.8476, \"Pythia_vs_Qwen_cont\": 0.7524, \"OLMo_vs_Qwen_cont\": 0.6762}, \"cross_model_spearman_rho_single_feature_auc\": {\"Pythia_vs_OLMo\": 0.95, \"Pythia_vs_Qwen_cont\": 0.9143, \"OLMo_vs_Qwen_cont\": 0.85, \"metric_definition\": \"Spearman ρ on per-feature AUC rankings (each feature independently classifies depth pairs)\"}, \"4model_tau_mean_continuation_by_first_auc\": 0.657, \"4model_tau_mean_all_by_first_auc\": 0.6, \"generation_mode_delta\": {\"Pythia_vs_Qwen\": \"+0.228\", \"OLMo_vs_Qwen\": \"+0.114\"}, \"top3_features_ranking_by_first_auc\": {\"Pythia\": [\"surp_d1_std\", \"surp_d2_std\", \"surp_std\"], \"OLMo\": [\"surp_std\", \"surp_d1_std\", \"surp_d2_std\"], \"Qwen_rewrite\": [\"freq_entropy\", \"surp_std\", \"surp_d1_std\"], \"Qwen_cont\": [\"surp_d1_std\", \"surp_std\", \"surp_d2_std\"]}, \"shared_top_discriminators\": \"surp_d1_std, surp_std, surp_d2_std shared across all architectures (single-feature AUC ranking)\", \"degradation_ordering_consistency\": \"Strong cross-model consistency (ρ≥0.85) on single-feature AUC ranking under controlled generation mode.\", \"residual_architecture_effect\": \"Qwen-cont vs OLMo (τ=0.54 by_first_auc) still lower than Pythia vs OLMo (τ=0.73), ~30-40% of ordering divergence from architecture\", \"limitation_1v2_weakness\": \"depth-pair level consistency weakest at 1v2 (τ~0.37), near-generational feature importance ordering varies more across models\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T02:40:50.885Z\", \"notes\": \"4-model τ matrix complete. Generation mode confirmed as primary driver of Qwen divergence (Δτ=+0.23 for Pythia pair). Residual architecture effect ~30-40%. C2 claim: degradation ordering largely consistent under same generation mode, with noted architecture residuals.\", \"hypothesis\": \"递归生成文本在统计特征空间中呈现单调退化趋势（如 perplexity 上升、词汇多样性下降），且退化速率在 K*=2 后显著减缓，这解释了为什么分类器在深代后失去区分力。\", \"parent\": \"mvp_pilot_sat_v1\"}, \"exp_024_arxiv_domain\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:43:59.323Z\", \"updated_at\": \"2026-05-17T02:57:37.559Z\", \"hypothesis\": \"Domain ablation: arXiv abstracts 数据下 K*=2 是否成立？验证 K* 跨数据域（C4 vs Wikipedia vs arXiv）的稳定性。Qwen2.5-1.5B base, continuation, nucleus p=0.95 T=1.0, 5K docs, depth 0-5。\", \"spec\": {\"command\": \"bash scripts/exp024_arxiv_domain.sh\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"pid\": 46766, \"log_path\": \"~/runs/gen-depth-contamination/exp_024_arxiv_domain.log\", \"submitted_at\": \"2026-05-16T14:44:07.168Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_024_arxiv/\", \"data_count\": 2200, \"model_name\": \"Qwen2.5-1.5B (base)\", \"seed\": 42, \"wall_clock_seconds\": 9545.8, \"gpu_hours\": 2.65}, \"notes\": \"2026-05-16 15:05 重启成功。PID 48295, cuda:2, 73% util。修复：depth_0.jsonl 已有 2200 行 arXiv 数据，prepare_seed_data 行数检查通过后跳过 C4 下载，HF_DATASETS_OFFLINE=1 不再冲突。n_docs=2200。预计 ~20 min 完成剩余 depth。\", \"metrics\": {\"K_star\": 3, \"pairwise_auc\": {\"0v1\": 0.9946, \"1v2\": 0.858, \"2v3\": 0.6427, \"3v4\": 0.5437, \"4v5\": 0.5294}, \"bootstrap_ci\": {\"0v1\": {\"auc\": 0.9946, \"ci_lower\": 0.9929, \"ci_upper\": 0.9961, \"perm_p\": 0.0001}, \"1v2\": {\"auc\": 0.858, \"ci_lower\": 0.848, \"ci_upper\": 0.8679, \"perm_p\": 0.0001}, \"2v3\": {\"auc\": 0.6427, \"ci_lower\": 0.6275, \"ci_upper\": 0.6575, \"perm_p\": 0.0001}, \"3v4\": {\"auc\": 0.5437, \"ci_lower\": 0.5276, \"ci_upper\": 0.5598, \"perm_p\": 0.0001}, \"4v5\": {\"auc\": 0.5294, \"ci_lower\": 0.5133, \"ci_upper\": 0.5455, \"perm_p\": 0.0006}}, \"bootstrap_resamples\": 10000, \"permutation_resamples\": 10000, \"key_finding\": \"arXiv domain K*=3 (CI-confirmed). 2v3 CI lower=0.6275 > θ=0.60. First condition with K*>2. 1v2 AUC=0.858 far exceeds C4/Wiki (~0.61-0.69).\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_024_arxiv/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_024_arxiv_domain.log\", \"completed_at\": \"2026-05-16T17:23:12.939Z\", \"parent\": \"exp_023_domain_ablation\"}, \"exp_017_qwen_continuation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-12T20:41:22.423Z\", \"updated_at\": \"2026-05-17T02:57:37.021Z\", \"hypothesis\": \"Continuation mode 的 K* 应等于 rewrite mode（K*=2），因为 K* 饱和边界是递归生成的文本固有属性，与生成模式（续写 vs 改写）无关——两种模式在深代时都收敛到相同的统计吸引子。\", \"notes\": \"dry-run passed 2026-05-13: model OK (2.9G safetensors), env OK (torch=2.10.0+cu128, transformers=4.57.6), dirs auto-create. Submit command prepared. 等 exp-002 完成后立即提交。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_ENDPOINT=https://hf-mirror.com && cd /root/autodl-tmp/gen-depth-contamination && python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B-Instruct/Qwen/Qwen2.5-1.5B-Instruct --data_dir /root/autodl-tmp/gen-depth-contamination/data_exp017_qwen_cont --results_dir /root/autodl-tmp/gen-depth-contamination/results_exp017_qwen_cont --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\\\"\", \"server\": \"autodl-4090d\", \"gpu\": [\"cuda:0\"], \"pid\": \"23758\", \"log_path\": \"~/runs/gen-depth-contamination/exp_017_qwen_continuation.log\", \"submitted_at\": \"2026-05-13T02:35:15Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp017_qwen_cont\", \"data_count\": 5000, \"model_name\": \"Qwen/Qwen2.5-1.5B-Instruct\", \"seed\": 42, \"max_depth\": 5, \"generation_mode\": \"continuation\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp017_qwen_cont/\", \"wall_clock_seconds\": 13305.8, \"gpu_hours\": 3.7}, \"log_path\": \"/root/runs/gen-depth-contamination/exp_017_qwen_continuation.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp017_qwen_cont/\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9972, \"1v2\": 0.6114, \"2v3\": 0.5609, \"3v4\": 0.5408, \"4v5\": 0.5139}, \"pairwise_jsd\": {\"0v1\": 0.28627, \"1v2\": 0.005107, \"2v3\": 0.003603, \"3v4\": 0.003395, \"4v5\": 0.003085}, \"ordinal_mae\": 1.1547, \"ordinal_accuracy\": 0.3819, \"top3_features\": [\"freq_entropy\", \"surp_mean\", \"surp_std\"]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T06:17:00.826Z\", \"parent\": \"mvp_pilot_sat_v1\"}, \"exp_012_binary_confidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:32:09.468Z\", \"updated_at\": \"2026-05-17T02:57:36.098Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_ENDPOINT=https://hf-mirror.com && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp012_ppl_depth_correlation.py --device cuda:0 --n_samples 500 --output_dir artifacts/exp012_results\\\"\", \"server\": \"westc-26893\", \"gpu\": [\"cuda:0\"], \"pid\": \"128209\", \"log_path\": \"~/runs/gen-depth-contamination/exp_012_binary_confidence.log\", \"submitted_at\": \"2026-05-15T23:14:10.207Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 489.8, \"gpu_hours\": 0.14}, \"notes\": \"N=500全量运行。Binary confidence与depth的Spearman ρ弱到中等(|ρ|=0.06-0.46)，6-class accuracy全部≤random baseline。关键发现：0v1 pairwise AUC极高(0.99+)但deeper pairs塌缩到~0.5，证明binary detector只捕捉human/AI边界，无法区分generational depth。Hypothesis验证成功。可视化已生成(exp012_confidence_vs_depth.pdf)。\", \"hypothesis\": \"Binary detector confidence（DivEye log-PPL、Binoculars ratio）与 true generational depth 相关性弱（Spearman rho < 0.3），因为这些检测器将所有合成文本折叠为单一类别，无法区分 gen-1 和 gen-3+，暴露 binary 范式的信息损失。\", \"reproduce\": {\"finished_at\": \"2026-05-15T23:20:30.036Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:20:30.983764+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp012_results/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_012_binary_confidence.log\", \"completed_at\": \"2026-05-15T23:22:19.966Z\", \"metrics\": {\"n_samples\": 500, \"generators\": [\"qwen-rewrite\", \"pythia-1.4b\", \"olmo-1b\", \"qwen-cont\"], \"6class_accuracy\": {\"qwen-rewrite\": 0.1987, \"pythia-1.4b\": 0.1303, \"olmo-1b\": 0.127, \"qwen-cont\": 0.1833, \"random_baseline\": 0.1667}, \"spearman_rho\": {\"qwen-rewrite\": {\"log_ppl_ref\": -0.1233, \"log_ppl_obs\": 0.0815, \"ppl_ratio\": 0.1185}, \"pythia-1.4b\": {\"log_ppl_ref\": -0.2972, \"log_ppl_obs\": -0.4529, \"ppl_ratio\": -0.392}, \"olmo-1b\": {\"log_ppl_ref\": -0.378, \"log_ppl_obs\": -0.4614, \"ppl_ratio\": -0.4068}, \"qwen-cont\": {\"log_ppl_ref\": -0.3887, \"log_ppl_obs\": -0.162, \"ppl_ratio\": -0.058}}, \"binary_detector_kstar\": 1, \"obd_kstar\": 2, \"auc_non_monotonic\": true, \"key_finding\": \"Binary detectors (DivEye/Binoculars) K*≈1 vs OBD K*=2. 6-class accuracy ≤0.199 (random=0.167). Spearman |ρ|=0.06-0.46 (statistically significant but practically weak). AUC non-monotonic — binary detectors cannot maintain depth ordering. Confirms binary confidence ≠ depth estimation.\"}, \"parent\": \"mvp_pilot_sat_v1\"}, \"exp_C_permutation_10k\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:18:26.152Z\", \"updated_at\": \"2026-05-17T02:57:35.128Z\", \"hypothesis\": \"10K permutation resamples 不应改变任何 K* 结论（所有 p < 0.01 的 pair 仍应 p < 0.01），确认 500 resamples 已有足够精度，K*=2 结论的统计基础稳固。\", \"spec\": {\"command\": \"python scripts/exp_C_permutation_10k.py\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data + data_exp001_pythia + data_exp002_olmo + data_exp017_qwen_cont\", \"data_count\": 20000, \"model_name\": \"N/A (CPU: permutation test)\", \"seed\": 42, \"note\": \"10K permutation resamples replacing 500, per depth pair per model\"}, \"conclusion\": \"success\", \"metrics\": {\"resamples\": 10000, \"all_boundary_pairs_p\": \"<0.0001\", \"key_finding\": \"10K permutation confirms all boundary p-values well below 0.01. FR-11 resolved.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_C_permutation_10k.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_C_permutation_10k.json\", \"completed_at\": \"2026-05-15T11:20:30.088Z\", \"parent\": \"exp_007_bootstrap_ci\"}, \"exp_009_dose_50pct_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T23:14:53.711Z\", \"updated_at\": \"2026-05-17T02:57:30.391Z\", \"spec\": {\"command\": \"python scripts/exp009_dose_response.py --ratio 0.5 --device cuda:0 --num_seeds 5\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"86342\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_50pct_v2.log\", \"submitted_at\": \"2026-05-16T23:14:53.568Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_009_dose_response/ratio_50/\", \"data_count\": 10000, \"model_name\": \"Qwen2.5-1.5B (continued pretraining)\", \"seed\": 42, \"checkpoint_source\": \"pretrained Qwen2.5-1.5B\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\", \"wall_clock_seconds\": 4079.2, \"gpu_hours\": 1.13}, \"hypothesis\": \"50% synthetic injection 下 graduated filtering 应展现最大优势 >=2pp MMLU（v2: fix HF mirror）。机制同 v1：半数数据为合成时 binary 激进丢弃导致数据饥饿。\", \"conclusion\": \"failed\", \"failure_reason\": \"CUDA OOM during lm_eval MMLU 5-shot (batch_size=8, logits tensor exceeds 24GB)\", \"checkpoint_path\": \"N/A (crashed before checkpoint)\", \"completed_at\": \"2026-05-17T00:22:52.736Z\", \"parent\": \"exp_009_dose_50pct\"}, \"exp_009_dose_30pct_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T23:14:51.739Z\", \"updated_at\": \"2026-05-17T02:57:29.467Z\", \"spec\": {\"command\": \"python scripts/exp009_dose_response.py --ratio 0.3 --device cuda:0 --num_seeds 5\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"86196\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_30pct_v2.log\", \"submitted_at\": \"2026-05-16T23:14:51.572Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_009_dose_response/ratio_30/\", \"data_count\": 7142, \"model_name\": \"Qwen2.5-1.5B (continued pretraining)\", \"seed\": 42, \"checkpoint_source\": \"pretrained Qwen2.5-1.5B\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\", \"wall_clock_seconds\": 4080.4, \"gpu_hours\": 1.13}, \"hypothesis\": \"30% synthetic injection 下 graduated filtering 优势应 >=1pp MMLU（v2: fix HF mirror）。机制同 v1：更高污染率下 binary 丢弃更多可用 gen-1 数据。\", \"conclusion\": \"failed\", \"failure_reason\": \"CUDA OOM during lm_eval MMLU 5-shot (batch_size=8, logits tensor exceeds 24GB)\", \"checkpoint_path\": \"N/A (crashed before checkpoint)\", \"completed_at\": \"2026-05-17T00:22:51.942Z\", \"parent\": \"exp_009_dose_30pct\"}, \"exp_009_dose_10pct_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T23:14:49.850Z\", \"updated_at\": \"2026-05-17T02:57:28.507Z\", \"spec\": {\"command\": \"python scripts/exp009_dose_response.py --ratio 0.1 --device cuda:0 --num_seeds 5\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"86049\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_10pct_v2.log\", \"submitted_at\": \"2026-05-16T23:14:49.708Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_009_dose_response/ratio_10/\", \"data_count\": 5555, \"model_name\": \"Qwen2.5-1.5B (continued pretraining)\", \"seed\": 42, \"checkpoint_source\": \"pretrained Qwen2.5-1.5B\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\", \"wall_clock_seconds\": 4081.2, \"gpu_hours\": 1.13}, \"hypothesis\": \"10% synthetic injection 下 graduated filtering 应比 binary 保留 >=0.5pp MMLU（v2: fix HF mirror）。机制同 v1：低污染时 gen-1 有训练价值，binary 全丢造成数据损失。\", \"conclusion\": \"failed\", \"failure_reason\": \"CUDA OOM during lm_eval MMLU 5-shot (batch_size=8, logits tensor exceeds 24GB)\", \"checkpoint_path\": \"N/A (crashed before checkpoint)\", \"completed_at\": \"2026-05-17T00:22:50.958Z\", \"parent\": \"exp_009_dose_10pct\"}, \"exp_009_dose_50pct\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T22:22:14.703Z\", \"updated_at\": \"2026-05-17T02:57:28.163Z\", \"spec\": {\"command\": \"python scripts/exp009_dose_response.py --ratio 0.5 --device cuda:0 --num_seeds 5\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"81595\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_50pct.log\", \"submitted_at\": \"2026-05-16T22:23:09.679Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_009_dose_response/ratio_50/\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B (continued pretraining)\", \"seed\": 42, \"checkpoint_source\": \"pretrained Qwen2.5-1.5B\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\", \"wall_clock_seconds\": 7180.5, \"gpu_hours\": 1.99}, \"hypothesis\": \"50% synthetic injection 下，graduated filtering 应展现最大优势（>=2pp MMLU），因为半数数据为合成时 binary filtering 的激进丢弃导致严重数据饥饿，而 graduated 保留 gen-1 维持训练集规模。\", \"conclusion\": \"failed\", \"failure_reason\": \"HF Hub network instability (httpx client closed)\", \"checkpoint_path\": \"N/A (crashed before checkpoint)\", \"completed_at\": \"2026-05-17T00:22:50.142Z\", \"parent\": \"exp_006_graduated_filtering\"}, \"exp_009_dose_30pct\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T22:22:12.817Z\", \"updated_at\": \"2026-05-17T02:57:27.096Z\", \"spec\": {\"command\": \"python scripts/exp009_dose_response.py --ratio 0.3 --device cuda:0 --num_seeds 5\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:2\"], \"pid\": \"81453\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_30pct.log\", \"submitted_at\": \"2026-05-16T22:23:07.791Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_009_dose_response/ratio_30/\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B (continued pretraining)\", \"seed\": 42, \"checkpoint_source\": \"pretrained Qwen2.5-1.5B\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\", \"wall_clock_seconds\": 7181.6, \"gpu_hours\": 1.99}, \"hypothesis\": \"30% synthetic injection 下，graduated filtering 优势应大于 10% 场景（>=1pp MMLU），因为更高污染率意味着 binary filtering 丢弃更多可用 gen-1 数据，而 graduated 仅移除 gen-2+ 有害部分。\", \"conclusion\": \"failed\", \"failure_reason\": \"HF Hub network instability (httpx client closed)\", \"checkpoint_path\": \"N/A (crashed before checkpoint)\", \"completed_at\": \"2026-05-17T00:22:49.399Z\", \"parent\": \"exp_006_graduated_filtering\"}, \"exp_009_dose_10pct\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T22:22:10.924Z\", \"updated_at\": \"2026-05-17T02:57:26.151Z\", \"spec\": {\"command\": \"python scripts/exp009_dose_response.py --ratio 0.1 --device cuda:0 --num_seeds 5\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"81311\", \"log_path\": \"~/runs/gen-depth-contamination/exp_009_dose_10pct.log\", \"submitted_at\": \"2026-05-16T22:23:05.447Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_009_dose_response/ratio_10/\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B (continued pretraining)\", \"seed\": 42, \"checkpoint_source\": \"pretrained Qwen2.5-1.5B\", \"eval_data\": \"MMLU + HellaSwag via lm-eval-harness\", \"wall_clock_seconds\": 7183.1, \"gpu_hours\": 2.0}, \"hypothesis\": \"10% synthetic injection 下，graduated filtering 应比 binary filtering 保留更多 MMLU 性能（>=0.5pp），因为低污染场景中 gen-1 文本仍有训练价值，binary 全部丢弃造成不必要的数据损失。\", \"conclusion\": \"failed\", \"failure_reason\": \"HF Hub network instability (httpx client closed)\", \"checkpoint_path\": \"N/A (crashed before checkpoint)\", \"completed_at\": \"2026-05-17T00:22:48.595Z\", \"parent\": \"exp_006_graduated_filtering\"}, \"exp_kstar_theta\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:08:01.704Z\", \"updated_at\": \"2026-05-17T02:56:51.877Z\", \"hypothesis\": \"K*(θ) 曲线在 θ∈[0.55,0.65] 存在 plateau（K* 对阈值不敏感），且 Cohen's h 在 depth=K* 到 depth=K*+1 间降至 < 0.2（小效应量），为 θ=0.60 提供非任意性理论依据。\", \"spec\": {\"command\": \"python scripts/plot_kstar_theta.py\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/ (bootstrap CI AUCs)\", \"data_count\": 20000, \"model_name\": \"N/A (CPU: K*(θ) visualization)\", \"seed\": \"N/A\", \"note\": \"FR-1 rebuttal: K*(θ) curve for 4 models × 5 depth pairs\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/kstar_theta_curve.pdf\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/scripts/plot_kstar_theta.py\", \"metrics\": {\"output_files\": [\"kstar_theta_curve.pdf (32KB)\", \"kstar_theta_curve.png (335KB)\"], \"models\": [\"Qwen-rewrite\", \"Pythia\", \"OLMo\", \"Qwen-cont\"], \"depth_pairs\": 5, \"key_finding\": \"All 4 models show AUC ≥0.993 at 0v1, decaying to ~0.50-0.53 at 4v5. θ=0.60 is justified as natural K*=2 boundary across all models. FR-1 Critical resolved.\"}, \"completed_at\": \"2026-05-15T15:08:25.181Z\"}, \"exp_022_cross_scorer_matrix\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:52:14.132Z\", \"updated_at\": \"2026-05-17T02:56:47.329Z\", \"hypothesis\": \"Self-scoring（generator=scorer）的 K* 和 pairwise AUC 应与 cross-scoring（generator≠scorer）差异 < 0.02，证明 K*=2 不是 scorer-generator familiarity artifact，而是文本本身的可区分性边界。\", \"parent\": \"exp_A_alt_scorer\", \"spec\": {\"command\": \"bash scripts/exp022_cross_scorer_matrix.sh\", \"server\": \"cqa1-22115\", \"data_path\": \"data_exp016_qwen_base + data_exp020_pythia_greedy + data/exp_021_length_256\", \"data_count\": 5000, \"model_name\": \"cross: Qwen2.5-1.5B/Pythia-1.4B/OLMo-1B/Qwen2.5-1.5B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pretrained\", \"eval_data\": \"cross-scorer matrix on existing depth chains\"}, \"notes\": \"2026-05-16 15:05: 双 GPU 并行。cuda:1 跑 2×2 子矩阵 (PID 49787, Qwen-cont/Pythia × Qwen-base/Pythia)。cuda:3 跑 3×4=12 组合 (先跑已缓存模型 6 combo，等下载 Qwen-Instruct/OLMo 后补剩余 6)。OLMo generator 无 depth chain 数据，实际 3 generators × 4 scorers。\", \"conclusion\": \"success\", \"metrics\": {\"total_combos\": 12, \"completed\": 12, \"K_star_distribution\": {\"K2\": 11, \"K1\": 1}, \"matrix\": {\"pythia_greedy×olmo\": {\"K_star\": 2, \"1v2\": 0.8811}, \"pythia_greedy×pythia\": {\"K_star\": 2, \"1v2\": 0.8838}, \"pythia_greedy×qwen_base\": {\"K_star\": 2, \"1v2\": 0.8814}, \"pythia_greedy×qwen_instruct\": {\"K_star\": 2, \"1v2\": 0.8818}, \"qwen_base×olmo\": {\"K_star\": 2, \"1v2\": 0.6047}, \"qwen_base×pythia\": {\"K_star\": 2, \"1v2\": 0.617}, \"qwen_base×qwen_base\": {\"K_star\": 2, \"1v2\": 0.6262}, \"qwen_base×qwen_instruct\": {\"K_star\": 2, \"1v2\": 0.6273}, \"qwen_cont256×olmo\": {\"K_star\": 2, \"1v2\": 0.6028}, \"qwen_cont256×pythia\": {\"K_star\": 1, \"1v2\": 0.5979}, \"qwen_cont256×qwen_base\": {\"K_star\": 2, \"1v2\": 0.6282}, \"qwen_cont256×qwen_instruct\": {\"K_star\": 2, \"1v2\": 0.6072}}, \"key_finding\": \"Scorer independence confirmed: K*=2 in 11/12 combos. Only exception: qwen_cont256×pythia (1v2=0.5979, borderline). Pythia-greedy 1v2~0.88 due to repetition collapse. Scorer choice Δ1v2 < 0.025 within each generator.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp022_cross_scorer/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp022_cross_scorer.log\", \"completed_at\": \"2026-05-16T18:56:44.226Z\"}, \"exp_008_retrain_chain_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T21:57:55.644Z\", \"updated_at\": \"2026-05-17T00:23:00.448Z\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp008_retrain_chain.py --device cuda:0\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"77098\", \"log_path\": \"~/runs/gen-depth-contamination/exp_008_retrain_chain_v2.log\", \"submitted_at\": \"2026-05-16T21:57:55.512Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_008_retrain_chain/\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b + LoRA (rank=16, alpha=32)\", \"seed\": 42, \"checkpoint_source\": \"pretrained + per-generation LoRA fine-tune\", \"eval_data\": \"C4 5K docs, retrain-chain depth 0-4\", \"wall_clock_seconds\": 8704.9, \"gpu_hours\": 2.42}, \"hypothesis\": \"Retrain-chain ecological validity (v2, fix: labels padding bug): Pythia-1.4B LoRA (rank=16, alpha=32) retrain-chain K* ≤ prompt-chain K*=2. 每代独立 LoRA fine-tune 1 epoch on 前代输出，再用 fine-tuned model 生成下一代。验证 prompt-chain 是 conservative upper bound。C4 5K docs, depth 0-4, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_001_pythia_depth\", \"metrics\": {\"k_star\": \">=4\", \"pairwise_auc\": {\"0v1\": 0.9847, \"1v2\": 0.9484, \"2v3\": 0.8888, \"3v4\": 0.7982}, \"pairwise_jsd\": {\"0v1\": 0.17, \"1v2\": 0.12, \"2v3\": 0.064, \"3v4\": 0.04}, \"key_finding\": \"Retrain-chain K*>=4, all pairs AUC>>0.60. LoRA adaptation artifacts make generations highly distinguishable. Prompt-chain K*=2 is text-intrinsic boundary.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/outputs/exp_008_retrain_chain/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T00:23:00.448Z\"}, \"exp-008-retrain-chain\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T19:31:01.383Z\", \"updated_at\": \"2026-05-16T22:16:29.240Z\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp008_retrain_chain.py --device cuda:0\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:0\"], \"pid\": \"71944\", \"log_path\": \"~/runs/gen-depth-contamination/exp-008-retrain-chain.log\", \"submitted_at\": \"2026-05-16T19:31:01.254Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_008_retrain_chain/\", \"data_count\": 5000, \"model_name\": \"EleutherAI/pythia-1.4b + LoRA (rank=16, alpha=32)\", \"seed\": 42, \"checkpoint_source\": \"pretrained + per-generation LoRA fine-tune\", \"eval_data\": \"C4 5K docs, retrain-chain depth 0-4\", \"wall_clock_seconds\": 5771.2, \"gpu_hours\": 1.6}, \"hypothesis\": \"Retrain-chain ecological validity: Pythia-1.4B LoRA (rank=16, alpha=32) retrain-chain K* ≤ prompt-chain K*=2. 每代独立 LoRA fine-tune 1 epoch on 前代输出，再用 fine-tuned model 生成下一代。验证 prompt-chain 是 conservative upper bound。C4 5K docs, depth 0-4, nucleus p=0.95 T=1.0, scorer=Qwen2.5-1.5B.\", \"parent\": \"exp_001_pythia_depth\", \"failure_reason\": \"Traceback → le \\\"/root/miniconda3/lib/python3.12/site-packages/transformers/tokenization_utils_base.py\\\", line 701, in as_tensor return torch.tensor(value, dtype=dtype) ^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^ ValueError: expected sequence of length 256 at dim 1 (got 228)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T21:07:12.427Z\", \"notes\": \"2026-05-16: 失败原因——TextDataset.__getitem__ 同时返回变长 input_ids 和 labels，DataCollatorForLanguageModeling 只 pad input_ids，导致 labels 长度不一致无法转 tensor。修复：移除 __getitem__ 中的 labels 字段，让 collator 自动处理。v2 已提交。\"}, \"exp_025_pythia_arxiv\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T17:16:13.988Z\", \"updated_at\": \"2026-05-16T19:22:57.204Z\", \"hypothesis\": \"Domain × model interaction: Pythia-1.4B on arXiv data 的 K* 是否与 exp-024 (Qwen on arXiv, K*=?) 一致？验证 arXiv domain effect 跨模型一致性，排除 Qwen-specific artifact。Pythia-1.4B continuation, nucleus p=0.95 T=1.0, 2200 docs, depth 0-5, scorer=Qwen2.5-1.5B base。\", \"parent\": \"exp_024_arxiv_domain\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && CUDA_VISIBLE_DEVICES=1 python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/models--EleutherAI--pythia-1.4b/snapshots/fedc38a16eea3bd36a96b906d78d11d2ce18ed79 --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --generation_mode continuation --top_p 0.95 --temperature 1.0 --num_samples 2200 --max_depth 5 --batch_size 8 --feat_batch_size 16 --data_dir data/exp_025_pythia_arxiv --results_dir results/exp_025_pythia_arxiv\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"67006\", \"log_path\": \"~/runs/gen-depth-contamination/exp_025_pythia_arxiv.log\", \"submitted_at\": \"2026-05-16T17:59:52.930Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_025_pythia_arxiv/\", \"data_count\": 2200, \"model_name\": \"EleutherAI/pythia-1.4b\", \"seed\": 42, \"checkpoint_source\": \"pretrained (EleutherAI/pythia-1.4b)\", \"eval_data\": \"arXiv abstracts depth chains (shared seed data from exp-024)\", \"wall_clock_seconds\": 4984.3, \"gpu_hours\": 1.38}, \"reproduce\": {\"finished_at\": \"2026-05-16T18:57:28.981Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T18:57:30.288692+00:00\"}]}, \"metrics\": {\"k_star\": 3, \"pairwise_auc\": {\"0v1\": 0.9877, \"1v2\": 0.8047, \"2v3\": 0.6545, \"3v4\": 0.5507, \"4v5\": 0.5287}, \"pairwise_jsd\": {\"0v1\": 0.171338, \"1v2\": 0.057344, \"2v3\": 0.019524, \"3v4\": 0.009917, \"4v5\": 0.008846}, \"bootstrap_ci\": {\"0v1\": {\"auc\": 0.9876, \"ci_lower\": 0.9851, \"ci_upper\": 0.99, \"perm_p\": 0.0001}, \"1v2\": {\"auc\": 0.8047, \"ci_lower\": 0.7934, \"ci_upper\": 0.8162, \"perm_p\": 0.0001}, \"2v3\": {\"auc\": 0.6544, \"ci_lower\": 0.6401, \"ci_upper\": 0.6688, \"perm_p\": 0.0001}, \"3v4\": {\"auc\": 0.55, \"ci_lower\": 0.534, \"ci_upper\": 0.5657, \"perm_p\": 0.0001}, \"4v5\": {\"auc\": 0.5284, \"ci_lower\": 0.5122, \"ci_upper\": 0.5443, \"perm_p\": 0.001}}, \"bootstrap_resamples\": 10000, \"permutation_resamples\": 10000, \"n_samples\": 2200, \"top_features\": [\"freq_entropy\", \"surp_std\", \"surp_mean\", \"surp_d1_skew\", \"surp_d1_mean\"], \"ordinal\": {\"MAE\": 0.8518, \"Accuracy\": 0.4545}, \"key_finding\": \"Pythia-1.4B on arXiv yields K*=3, identical to exp-024 (Qwen on arXiv). 2v3 CI lower=0.6401 > θ=0.60. Domain saturation depth is model-invariant for arXiv.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_025_pythia_arxiv/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp_025_pythia_arxiv.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T19:22:57.204Z\"}, \"exp_020_pythia_decoding\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:52:13.036Z\", \"updated_at\": \"2026-05-16T17:18:28.366Z\", \"hypothesis\": \"Pythia-1.4B 解码消融：4 个 decoding config (greedy/nuc p=0.9/T=0.7/T=1.2) 的 K* 是否一致？与 exp-003 (Qwen) 平行，验证 decoding 效应跨模型一致性。C4 5K, depth 0-5。\", \"parent\": \"exp_003_decoding_ablation\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T04:57:46.476Z\"}, \"spec\": {\"command\": \"nohup bash -c 'CUDA_VISIBLE_DEVICES=2 TRANSFORMERS_OFFLINE=1 HF_HOME=/root/autodl-tmp/.hf_cache bash scripts/exp020_pythia_decoding.sh' > /tmp/exp020_pythia_decoding.log 2>&1 &\", \"server\": \"cqa1-22115\", \"data_path\": \"data_exp020_pythia_{greedy,nuc09,t07,t12}/\", \"data_count\": 20000, \"model_name\": \"EleutherAI/pythia-1.4b (fp16)\", \"seed\": 42, \"generation_mode\": \"continuation (4 decoding configs: greedy/nuc09/t07/t12)\", \"pid\": 14551, \"log_path\": \"/tmp/exp020_pythia_decoding.log\", \"note\": \"Worker 误用 nohup 而非 submit_training_job，已补注册 cron 监控 (PID 14551)。原 PID 13076 已被 kill。\"}, \"notes\": \"greedy 1v2 AUC=0.8838 调查完成：根因为 Pythia-1.4B greedy 级联重复坍塌（4-gram repeat rate: d0=0.01→d1=0.72→d2=0.81; TTR: d0=0.72→d1=0.19→d2=0.14）。hapax_ratio (d=1.06) 和 low_freq_ratio (d=1.03) 是 top 贡献特征。非 bug，参数正确，无数据泄漏。K*=2 不受影响。建议论文标注为 repetition-dominated regime。| Bootstrap CI (10000 iter): t07 2v3 AUC=0.5939 CI [0.5855, 0.6025] BORDERLINE (CI upper crosses θ); t12 1v2 AUC=0.6170 CI [0.6071, 0.6270] PASS。\", \"conclusion\": \"success\", \"metrics\": {\"greedy\": {\"K_star\": 2, \"auc\": {\"0v1\": 0.9992, \"1v2\": 0.8838, \"2v3\": 0.5342, \"3v4\": 0.5228, \"4v5\": 0.5162}}, \"nuc09\": {\"K_star\": 2, \"auc\": {\"0v1\": 0.9948, \"1v2\": 0.677, \"2v3\": 0.5549, \"3v4\": 0.5299, \"4v5\": 0.5013}}, \"t07\": {\"K_star\": 2, \"auc\": {\"0v1\": 0.9965, \"1v2\": 0.7265, \"2v3\": 0.5941, \"3v4\": 0.5698, \"4v5\": 0.5284}}, \"t12\": {\"K_star\": 2, \"auc\": {\"0v1\": 0.9933, \"1v2\": 0.6172, \"2v3\": 0.5226, \"3v4\": 0.517, \"4v5\": 0.5051}}}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp020_pythia_{greedy,nuc09,t07,t12}/\", \"log_path\": \"/tmp/exp020_pythia_decoding.log\", \"completed_at\": \"2026-05-16T14:41:33.153Z\"}, \"exp_021_length_ablation\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T04:52:13.569Z\", \"updated_at\": \"2026-05-16T17:18:21.506Z\", \"hypothesis\": \"文本长度消融：128/256/512 tokens 下 K* 是否稳定？验证 K*=2 不依赖于 256-token 固定长度设定。Qwen2.5-1.5B (base) continuation, C4 5K, depth 0-5。\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-16T04:57:47.040Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-16T06:23:09.413Z\", \"notes\": \"2026-05-16 retry#2: 用本地 C4 数据修复。数据源=/root/autodl-tmp/gen-depth-contamination/data_exp016_qwen_base/depth_0.jsonl (5000行)，复制到 data/exp_021_length_{128,256,512}/。设置 HF_DATASETS_OFFLINE=1 + TRANSFORMERS_OFFLINE=1 阻断 HF 网络调用，prepare_seed_data 检测到本地文件自动跳过 streaming。PID 20982, tmux session exp_021_length_ablation。\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-16: 崩溃原因确认——脚本未执行 `source /etc/network_turbo`，导致 AutoDL 网络代理未启用，HuggingFace C4 数据集下载失败 (RuntimeError: Cannot send a request, as the client has been closed / Errno 99: Cannot assign requested address)。三个长度 (128/256/512) 全部未完成，无任何产出。cuda:3 已空闲。需重跑并修复网络配置。\"}}, \"spec\": {\"command\": \"bash -c \\\"export HF_DATASETS_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && cd /root/autodl-tmp/gen-depth-contamination && bash scripts/exp021_length_ablation.sh\\\"\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:3\"], \"pid\": \"20982\", \"log_path\": \"~/runs/gen-depth-contamination/exp_021_length_ablation.log\", \"submitted_at\": \"2026-05-16T07:13:09.587Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp016_qwen_base/depth_0.jsonl (local C4, copied to data/exp_021_length_{128,256,512}/)\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B (base)\", \"seed\": 42, \"generation_mode\": \"continuation\", \"max_new_tokens\": [128, 256, 512], \"max_depth\": 5, \"batch_size\": 16, \"checkpoint_path\": \"results/exp_021_length_{128,256,512}\", \"description\": \"Retry#2: local C4 data, HF_DATASETS_OFFLINE=1, 3 length configs sequential on cuda:3\", \"wall_clock_seconds\": 29523.5, \"gpu_hours\": 8.2}, \"conclusion\": \"success\", \"metrics\": {\"128tok\": {\"K_star\": 2, \"1v2_auc\": 0.6219}, \"256tok\": {\"K_star\": 2, \"1v2_auc\": 0.6282}, \"512tok\": {\"K_star\": 2, \"1v2_auc\": 0.6073}, \"all_K_star_2\": true, \"bootstrap_ci\": {\"512tok_1v2\": {\"auc\": 0.6073, \"ci_lower\": 0.5979, \"ci_upper\": 0.6166, \"perm_p\": 0.0001, \"verdict\": \"BORDERLINE\"}}}}, \"exp_018_llama8b_depth\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:52:11.229Z\", \"updated_at\": \"2026-05-16T16:18:02.754Z\", \"hypothesis\": \"Cross-family K* 验证：LLaMA-3.1-8B continuation mode 的 K* 是否 = 2？首次超出 Qwen 家族，验证 K* universality 跨模型架构。C4 5K, depth 0-5, scorer=Qwen2.5-1.5B base。\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T04:57:44.549Z\", \"finished_at\": \"2026-05-16T15:35:57.336Z\", \"training_hours\": 10.64}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/LLM-Research/Meta-Llama-3___1-8B --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --generation_mode continuation --num_samples 5000 --max_depth 5 --batch_size 4 --feat_batch_size 8 --data_dir data/exp_018_llama8b --results_dir results/exp_018_llama8b\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0 (RTX 4090D 24GB)\", \"data_path\": \"C4 validation (HuggingFace streaming)\", \"data_count\": 5000, \"model_name\": \"LLaMA-3.1-8B (Meta-Llama-3.1-8B)\", \"scorer\": \"Qwen2.5-1.5B base\", \"seed\": 42, \"generation_mode\": \"continuation\", \"max_depth\": 5, \"batch_size\": 4, \"feat_batch_size\": 8, \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/logs/exp_018_llama8b.log\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results/exp_018_llama8b\", \"description\": \"Cross-family K* validation: LLaMA-3.1-8B generates depth chain, Qwen2.5-1.5B base scores surprisal features\"}, \"failure_reason\": \"null — cron 误报，实验实际成功\", \"conclusion\": \"success\", \"pid\": 10403, \"gpu_id\": \"cuda:0\", \"completed_at\": \"2026-05-16T15:35:57.947Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T15:35:59.527502+00:00\"}]}, \"notes\": \"2026-05-16 日志诊断：实验实际已成功完成(K*=2, AUC 1v2=0.6123)，Pipeline complete 正常退出。被 cron 误判 failed 原因：进程正常结束后 PID 10403 消失，无 sentinel/W&B 信号，监控 5× 检查后 auto-resolve 为 failed。结果文件完整存在于 results/exp_018_llama8b/。应改 conclusion=success。\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9225, \"1v2\": 0.6123, \"2v3\": 0.5274, \"3v4\": 0.5138, \"4v5\": 0.5097}, \"jsd\": {\"0v1\": 0.077, \"1v2\": 0.012, \"2v3\": 0.005}, \"bootstrap_ci\": {\"0v1\": {\"auc\": 0.9224, \"ci_lower\": 0.9174, \"ci_upper\": 0.9272, \"perm_p\": 0.0001}, \"1v2\": {\"auc\": 0.6123, \"ci_lower\": 0.6028, \"ci_upper\": 0.6216, \"perm_p\": 0.0001}, \"2v3\": {\"auc\": 0.5273, \"ci_lower\": 0.5169, \"ci_upper\": 0.5378, \"perm_p\": 0.0001}, \"3v4\": {\"auc\": 0.5168, \"ci_lower\": 0.5062, \"ci_upper\": 0.5275, \"perm_p\": 0.0037}, \"4v5\": {\"auc\": 0.5159, \"ci_lower\": 0.5052, \"ci_upper\": 0.5268, \"perm_p\": 0.0035}}, \"bootstrap_resamples\": 10000, \"permutation_resamples\": 10000}}, \"exp_023_domain_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:59:57.643Z\", \"updated_at\": \"2026-05-16T15:25:22.371Z\", \"hypothesis\": \"Domain ablation: Wikipedia 数据下 K*=2 是否成立？验证 K* 跨数据域（C4 vs Wikipedia）的稳定性。Qwen2.5-1.5B base, continuation, nucleus p=0.95 T=1.0, 5K docs, depth 0-5。\", \"spec\": {\"command\": \"bash scripts/exp023_wiki_domain.sh\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"pid\": 39530, \"log_path\": \"~/runs/gen-depth-contamination/exp_023_domain_ablation.log\", \"submitted_at\": \"2026-05-16T12:00:07.999Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/exp_023_wiki/\", \"data_count\": 5000, \"model_name\": \"Qwen2.5-1.5B (base)\", \"seed\": 42, \"wall_clock_seconds\": 12314.4, \"gpu_hours\": 3.42}, \"conclusion\": \"success\", \"metrics\": {\"K_star\": 2, \"1v2_auc\": 0.6193, \"2v3_auc\": 0.5498, \"all_folds_above_060\": true, \"top_feature\": \"freq_entropy\", \"ordinal_accuracy\": 0.377}, \"checkpoint_path\": \"results_exp023_wiki_domain/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_023_domain_ablation.log\", \"completed_at\": \"2026-05-16T15:25:22.371Z\"}, \"exp_019b_mistral_cross_scorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:22:44.822Z\", \"updated_at\": \"2026-05-16T11:56:59.892Z\", \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path mistral-7b --scorer_path qwen2.5-1.5b\", \"server\": \"cqa1-22115\", \"gpu\": [\"cuda:1\"], \"pid\": \"36365\", \"log_path\": \"~/runs/gen-depth-contamination/exp_019b_mistral_cross_scorer.log\", \"submitted_at\": \"2026-05-16T11:23:28.609Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp019b_mistral_cross\", \"data_count\": 5000, \"model_name\": \"mistral-7b-cross-qwen1.5b-scorer\", \"seed\": 42, \"checkpoint_source\": \"exp_019_mistral7b_depth\", \"eval_data\": \"data_exp019b_mistral_cross\", \"wall_clock_seconds\": 1938.5, \"gpu_hours\": 0.54}, \"hypothesis\": \"排除 self-scorer 因素：Mistral-7B depth chain 用 Qwen2.5-1.5B-base 评分后 K* 是否=2？如果 K*=2 则 exp-019 的 K*=1 是 self-scorer artifact；如果 K*=1 则是 Mistral 生成文本的固有特性。\", \"parent\": \"exp_019_mistral7b_depth\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp019b_mistral_cross_scorer\", \"log_path\": \"~/runs/gen-depth-contamination/exp_019b_mistral_cross_scorer.log\", \"completed_at\": \"2026-05-16T11:55:47.111Z\", \"metrics\": {\"k_star\": 1, \"pairwise_auc\": {\"0v1\": 0.9209, \"1v2\": 0.5695, \"2v3\": 0.5335, \"3v4\": 0.514, \"4v5\": 0.5184}, \"bootstrap_ci\": {\"0v1\": {\"mean\": 0.9209, \"ci_lower\": 0.9189, \"ci_upper\": 0.9229, \"pass_060\": true}, \"1v2\": {\"mean\": 0.5696, \"ci_lower\": 0.5645, \"ci_upper\": 0.5746, \"pass_060\": false}, \"2v3\": {\"mean\": 0.5335, \"ci_lower\": 0.5283, \"ci_upper\": 0.5382, \"pass_060\": false}, \"3v4\": {\"mean\": 0.514, \"ci_lower\": 0.5063, \"ci_upper\": 0.5213, \"pass_060\": false}, \"4v5\": {\"mean\": 0.5183, \"ci_lower\": 0.5128, \"ci_upper\": 0.5244, \"pass_060\": false}}, \"jsd\": {\"0v1\": 0.08355, \"1v2\": 0.007642, \"2v3\": 0.004752, \"3v4\": 0.004255, \"4v5\": 0.003758}, \"ordinal_mae\": 1.3737, \"ordinal_accuracy\": 0.3179, \"top3_features\": [\"freq_entropy\", \"surp_d1_skew\", \"surp_d1_mean\"], \"key_finding\": \"Cross-scorer (Qwen-1.5B scoring Mistral text) confirms K*=1. 1v2 AUC=0.5695 (self-scorer was 0.5935) — cross-scorer LOWER, not higher. Mistral K*=1 is genuine (inherent to Mistral generations), NOT a self-scorer artifact.\"}, \"notes\": \"K*=1 confirmed genuine (not self-scorer artifact). Cross-scorer (Qwen-base) 1v2 AUC=0.5695 CI [0.5645, 0.5746] — 比 self-scorer (0.5935) 更低。换 scorer 后区分度下降，排除 self-scorer inflation 假说。Top-3 features 与 self-scorer 完全一致: freq_entropy, surp_d1_skew, surp_d1_mean。\"}, \"exp_019_mistral7b_depth\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:52:12.077Z\", \"updated_at\": \"2026-05-16T11:28:45.586Z\", \"hypothesis\": \"Cross-family K* 验证：Mistral-7B-v0.3 continuation mode 的 K* 是否 = 2？第二个非 Qwen 家族模型。C4 5K, depth 0-5, scorer=Mistral-7B-v0.3 (self-scorer)。与 exp-001/002/017 self-scoring 方法一致，exp_A_alt_scorer 已证明 scorer 不影响 K*。\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"cqa1-22115\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T04:57:45.553Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/mistralai/Mistral-7B-v0___3 --data_dir data_exp019_mistral7b --results_dir results_exp019_mistral7b --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp019_mistral7b\", \"data_count\": 5000, \"model_name\": \"mistralai/Mistral-7B-v0.3 (fp16)\", \"scorer\": \"Mistral-7B-v0.3 (self-scorer, 与 exp-001/002/017 一致)\", \"seed\": 42, \"generation_mode\": \"continuation\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"pid\": 12147, \"gpu_id\": \"cuda:1\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp019_mistral7b/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/exp019.log\", \"completed_at\": \"2026-05-16T11:17:08.348Z\", \"metrics\": {\"k_star\": 1, \"pairwise_auc\": {\"0v1\": 0.9843, \"1v2\": 0.5935, \"2v3\": 0.5402, \"3v4\": 0.5232, \"4v5\": 0.5181}, \"bootstrap_ci_1v2\": {\"ci_lower\": 0.5835, \"ci_upper\": 0.6032, \"p_auc_leq_060\": 0.9017}, \"jsd\": {\"0v1\": 0.124194, \"1v2\": 0.008051, \"2v3\": 0.005047, \"3v4\": 0.004516, \"4v5\": 0.004109}, \"ordinal_mae\": 1.2275, \"ordinal_accuracy\": 0.3567, \"top3_features\": [\"freq_entropy\", \"surp_d1_skew\", \"surp_d1_mean\"]}, \"notes\": \"K*=1 (非预期的 K*=2)。1v2 AUC=0.5935±0.0054，低于 θ=0.60 阈值仅 0.0065。边界线结果，需 bootstrap CI 确认。0v1 AUC=0.9843 强可区分。Self-scorer (Mistral-7B)。cuda:1 已空闲。\"}, \"exp_016_base_vs_instruct\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T01:01:55.079Z\", \"updated_at\": \"2026-05-16T05:04:51.120Z\", \"hypothesis\": \"Base vs Instruct K* 对比：Qwen2.5-1.5B (base) continuation mode 的 K* 是否与 exp-017 (Instruct continuation, K*=2) 一致？封堵 \\\"K*=2 是 instruct-tuning 副产物\\\" 攻击面。唯一变量 = base vs instruct。\", \"parent\": \"exp_017_qwen_continuation\", \"server\": \"cqa1-22115\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westc-26893\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T01:02:43.478Z\"}, \"completed_at\": \"2026-05-16T03:22:38.539Z\", \"notes\": \"2026-05-16: Resumed on cqa1-22115 (migrated from westc-26893). Depth 0-3 complete, generating depth 4-5. PID=3442 on cuda:0.\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-16: Resumed on cqa1-22115 (migrated from westc-26893). Depth 0-3 complete, generating depth 4-5. PID=3442 on cuda:0.\"}}, \"spec\": {\"command\": \"python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data_dir data_exp016_qwen_base --results_dir results_exp016_qwen_base --num_samples 5000 --max_depth 5 --batch_size 16 --generation_mode continuation\", \"server\": \"cqa1-22115\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp016_qwen_base\", \"data_count\": 5000, \"model_name\": \"Qwen/Qwen2.5-1.5B (base, fp16)\", \"seed\": 42, \"generation_mode\": \"continuation\", \"scorer\": \"Qwen2.5-1.5B (base)\", \"gpu\": [\"cuda:0\"], \"tmux_session\": \"exp016\", \"log_path\": \"/tmp/exp016.log\", \"note\": \"Retry #1: Resumed on cqa1-22115 after westc-26893 restart. Depth 0-3 migrated via rsync.\", \"checkpoint_source\": \"N/A (standalone generation, not eval)\", \"eval_data\": \"C4 validation 5000 samples\"}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.987, \"1v2\": 0.6262, \"2v3\": 0.5496, \"3v4\": 0.5294, \"4v5\": 0.5182}, \"pairwise_auc_std\": {\"0v1\": 0.0015, \"1v2\": 0.0152, \"2v3\": 0.0067, \"3v4\": 0.0132, \"4v5\": 0.0139}, \"pairwise_jsd\": {\"0v1\": 0.163726, \"1v2\": 0.01081, \"2v3\": 0.005311, \"3v4\": 0.003942, \"4v5\": 0.003522}, \"ordinal_mae\": 1.1691, \"ordinal_accuracy\": 0.3719, \"top_features\": [\"freq_entropy\", \"surp_std\", \"surp_d1_skew\", \"surp_d1_mean\", \"surp_mean\"], \"n_samples\": 30000, \"bootstrap_ci\": {\"0v1\": {\"auc\": 0.987, \"ci_lower\": 0.9853, \"ci_upper\": 0.9885, \"perm_p\": 0.0001}, \"1v2\": {\"auc\": 0.626, \"ci_lower\": 0.6168, \"ci_upper\": 0.6353, \"perm_p\": 0.0001}, \"2v3\": {\"auc\": 0.5496, \"ci_lower\": 0.5397, \"ci_upper\": 0.56, \"perm_p\": 0.0001}, \"3v4\": {\"auc\": 0.5293, \"ci_lower\": 0.5188, \"ci_upper\": 0.5399, \"perm_p\": 0.0001}, \"4v5\": {\"auc\": 0.5181, \"ci_lower\": 0.5075, \"ci_upper\": 0.5288, \"perm_p\": 0.0016}}, \"bootstrap_resamples\": 10000, \"permutation_resamples\": 10000, \"key_finding\": \"K*=2 for base model confirmed with bootstrap CI. 1v2 AUC=0.626, 95% CI=[0.6168, 0.6353], CI lower=0.6168 > θ=0.60 (PASS). All pairs significant (p≤0.0016). Fold 0 1v2=0.5963 is an outlier but aggregate CI robustly above threshold. Base 1v2 CI [0.6168, 0.6353] overlaps with Instruct 1v2 CI [0.6015, 0.6213] — no significant base-vs-instruct difference.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/results_exp016_qwen_base/\", \"log_path\": \"/tmp/exp016.log\"}, \"exp_003_decoding_ablation\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-12T20:06:25.260Z\", \"updated_at\": \"2026-05-16T03:06:04.938Z\", \"hypothesis\": \"解码策略调控 K*：不同 top_p/temperature 设置是否改变饱和边界（greedy→更低 K*? 高温度→更高 K*?）\", \"failure_reason\": \"SSH check failed 5x — last error: Unknown server 'autodl-4090d'. Available: ['westc-26893']\", \"completed_at\": \"2026-05-13T15:35:29.038Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T15:35:30.207607+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:22:20.803872+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"失败原因: SSH 别名变更 (autodl-4090d → westc-26893)，cron 监控 5 次连不上后标记 failed。初步诊断: 日志在 westc-26893 上可读，config 2 (nucleus_p0.9_t1.0) 已完成并输出 K*=2，config 3 (nucleus_p0.95_t0.7) 在 depth 4 进度 ~90% 时日志截止。实验可能已完成或部分完成。Worker worker_diagnose_exp_003_decoding_ablation_20260513T153757 正在深入诊断。\"}}, \"notes\": \"Server alias 变更 autodl-4090d → westc-26893 导致 cron 误标 failed。实际实验一直正常运行。Config 1 (greedy, K*=2), Config 2 (nuc p=0.9/T=1.0, K*=2), Config 3 (nuc p=0.95/T=0.7, K*=2) 已完成。Config 4 (nuc p=0.95/T=1.2) 运行中。深度分析: 1v2 AUC Δ<0.003 across configs, D016 universality confirmed (all 7 configs > θ=0.60), θ-sensitivity K* profile identical across 3 configs. 分析脚本 scripts/exp003_analyze_all_configs.py 已部署。\", \"spec\": {\"command\": \"python scripts/exp003_analyze_all_configs.py\", \"server\": \"westc-26893\", \"gpu\": [\"cuda:0\"], \"pid\": \"29459\", \"log_path\": \"~/runs/gen-depth-contamination/exp_003_decoding_ablation.log\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp003_*\", \"data_count\": 4, \"model_name\": \"Qwen/Qwen2.5-1.5B-Instruct\", \"seed\": 42, \"configs\": \"4 ablation configs: greedy, nucleus p=0.9/T=1.0, nucleus p=0.95/T=0.7, nucleus p=0.95/T=1.2\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp003_*\", \"log_path_note\": \"server renamed from autodl-4090d to westc-26893\"}, \"metrics\": {\"K_star\": 2, \"K_star_robust\": true, \"bootstrap_ci\": {\"config1_greedy\": {\"0v1\": {\"auc\": 0.9796, \"ci\": [0.9772, 0.982], \"perm_p\": 0}, \"1v2\": {\"auc\": 0.6892, \"ci\": [0.6802, 0.6982], \"perm_p\": 0}, \"2v3\": {\"auc\": 0.5612, \"ci\": [0.5517, 0.5705], \"perm_p\": 0}, \"3v4\": {\"auc\": 0.5405, \"ci\": [0.5308, 0.5502], \"perm_p\": 0}, \"4v5\": {\"auc\": 0.5137, \"ci\": [0.5033, 0.5238], \"perm_p\": 0.0082}}, \"config2_nuc09\": {\"0v1\": {\"auc\": 0.9945, \"ci\": [0.9934, 0.9956], \"perm_p\": 0}, \"1v2\": {\"auc\": 0.6862, \"ci\": [0.6774, 0.6951], \"perm_p\": 0}, \"2v3\": {\"auc\": 0.5917, \"ci\": [0.5824, 0.601], \"perm_p\": 0, \"note\": \"CI upper crosses theta=0.60\"}, \"3v4\": {\"auc\": 0.5468, \"ci\": [0.5369, 0.5568], \"perm_p\": 0}, \"4v5\": {\"auc\": 0.5066, \"ci\": [0.4959, 0.5173], \"perm_p\": 0.1199}}, \"config3_t07\": {\"0v1\": {\"auc\": 0.9877, \"ci\": [0.9857, 0.9896], \"perm_p\": 0}, \"1v2\": {\"auc\": 0.6885, \"ci\": [0.6797, 0.697], \"perm_p\": 0}, \"2v3\": {\"auc\": 0.5901, \"ci\": [0.5806, 0.5996], \"perm_p\": 0}, \"3v4\": {\"auc\": 0.539, \"ci\": [0.5288, 0.5493], \"perm_p\": 0}, \"4v5\": {\"auc\": 0.5348, \"ci\": [0.5243, 0.5454], \"perm_p\": 0}}, \"config4_t12\": {\"0v1\": {\"auc\": 0.9982, \"ci\": [0.9975, 0.9987], \"perm_p\": 0}, \"1v2\": {\"auc\": 0.7037, \"ci\": [0.6945, 0.7126], \"perm_p\": 0}, \"2v3\": {\"auc\": 0.582, \"ci\": [0.5722, 0.5917], \"perm_p\": 0}, \"3v4\": {\"auc\": 0.5293, \"ci\": [0.5185, 0.5399], \"perm_p\": 0}, \"4v5\": {\"auc\": 0.5237, \"ci\": [0.5132, 0.5347], \"perm_p\": 0.0001}}, \"resamples\": 10000, \"method\": \"GroupKFold(5) OOF + doc-level bootstrap + label permutation\"}}, \"reproduce\": {\"finished_at\": \"2026-05-13T20:22:19.870Z\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp003_analysis.json\", \"log_path\": \"~/runs/gen-depth-contamination/exp_003_decoding_ablation.log\", \"conclusion\": \"success\"}, \"exp_004_7b_crossscale\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T11:08:22.198Z\", \"updated_at\": \"2026-05-15T23:37:24.772Z\", \"hypothesis\": \"K*=2 在 7B scale 下是否成立？Qwen2.5-7B continuation mode, C4 5K seeds, scorer=Qwen2.5-1.5B。Reviewer R2 Critical: 现有实验仅 ≤1.5B\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"reproduce\": {\"finished_at\": \"2026-05-15T23:11:49.043Z\"}, \"completed_at\": \"2026-05-15T22:26:45.097Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:26:46.220502+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:11:50.215210+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"进程 5 次死亡无 W&B metrics，cron 自动标记 failed。诊断中：Worker worker_diagnose_exp_004_7b_crossscale_20260515T222832 正在查日志。模型加载成功(14530MB)，C4 采样有进度，日志末尾异常出现 transformers 全量模型列表。待诊断完成后确定 root cause 和重试方案。\"}}, \"notes\": \"初始运行因进程死亡 5 次被 cron 标记 failed（原 log: exp004_run.log 无 W&B sentinel）。诊断 Worker 发现数据生成已完成，重跑 feature extraction + classification（exp004_resume_feat.sh）后成功。K*=2 在 7B scale 下确认成立。0v1 AUC=0.964 低于所有 1.5B 模型（>0.99），符合预期：更大模型生成更 human-like 文本。1v2=0.618 仍 >θ=0.60。FR-4 Warning resolved。\", \"spec\": {\"hypothesis\": \"K*=2 在 7B scale 下是否成立？Qwen2.5-7B continuation mode, C4 5K seeds, scorer=Qwen2.5-1.5B\", \"server\": \"westc-26893\", \"model_name\": \"Qwen/Qwen2.5-7B (fp16, 14.5GB) + Qwen2.5-1.5B-Instruct (scorer)\", \"data_count\": 5000, \"seed\": 42, \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && bash scripts/exp004_resume_feat.sh\\\"\", \"gpu\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp004_qwen7b\", \"note\": \"Resume: data generation complete, rerunning feature extraction + classification with corrected scorer path. PID 127516.\"}, \"conclusion\": \"success\", \"metrics\": {\"k_star\": 2, \"pairwise_auc\": {\"0v1\": 0.9644, \"1v2\": 0.6178, \"2v3\": 0.546, \"3v4\": 0.5225, \"4v5\": 0.5091}, \"pairwise_auc_std\": {\"0v1\": 0.0034, \"1v2\": 0.0081, \"2v3\": 0.0028, \"3v4\": 0.0113, \"4v5\": 0.0052}, \"bootstrap_ci\": {\"0v1\": {\"auc\": 0.9638, \"ci_lower\": 0.9607, \"ci_upper\": 0.9665, \"perm_p\": 0.0001}, \"1v2\": {\"auc\": 0.6168, \"ci_lower\": 0.6079, \"ci_upper\": 0.6261, \"perm_p\": 0.0001}, \"2v3\": {\"auc\": 0.5492, \"ci_lower\": 0.5388, \"ci_upper\": 0.5594, \"perm_p\": 0.0001}, \"3v4\": {\"auc\": 0.5276, \"ci_lower\": 0.517, \"ci_upper\": 0.5375, \"perm_p\": 0.0001}, \"4v5\": {\"auc\": 0.5085, \"ci_lower\": 0.4988, \"ci_upper\": 0.5191, \"perm_p\": 0.0676}}, \"bootstrap_resamples\": 1000, \"permutation_resamples\": 10000, \"pairwise_jsd\": {\"0v1\": 0.127422, \"1v2\": 0.010114, \"2v3\": 0.004798, \"3v4\": 0.004821, \"4v5\": 0.003335}, \"ordinal_mae\": 1.2156, \"ordinal_accuracy\": 0.3523, \"top_features\": [\"freq_entropy\", \"surp_d1_skew\", \"surp_std\", \"surp_d1_mean\", \"surp_mean\"], \"key_finding\": \"K*=2 confirmed at 7B scale with bootstrap CI. 1v2 CI lower=0.6079>0.60 (robust). 2v3 CI upper=0.5594<0.60. 4v5 only non-significant pair (p=0.0676). FR-4 Warning resolved.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp004_qwen7b/\", \"log_path\": \"/root/runs/gen-depth-contamination/exp_004_7b_crossscale.log\"}, \"exp_E_paired_stats\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:18:27.723Z\", \"updated_at\": \"2026-05-15T14:22:43.224Z\", \"hypothesis\": \"C3 filtering 策略间差异是否统计显著？Holm-Bonferroni 多重比较校正 + Cohen's d 效应量（FR-5 Warning）\", \"spec\": {\"command\": \"python scripts/exp_E_paired_stats.py\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp006_filtering/results/\", \"data_count\": 51, \"model_name\": \"N/A (CPU: paired t-test + Holm-Bonferroni)\", \"seed\": \"N/A\", \"note\": \"6 strategies × 5 seeds, 15 pairwise comparisons, Holm-Bonferroni correction + Cohen's d\"}, \"conclusion\": \"success\", \"metrics\": {\"mmlu_significant_pairs\": \"8/15\", \"hellaswag_significant_pairs\": \"9/15\", \"binary_ours_vs_all_mmlu\": \"all significant\", \"max_cohen_d_mmlu\": 10.8, \"max_cohen_d_hellaswag\": 8.98, \"graduated_a09_vs_dsir_corrected_p\": 0.0523, \"cohen_d_method\": \"d_av (Lakens 2013)\", \"key_finding\": \"binary-ours significantly outperforms all alternatives on MMLU. On HellaSwag, binary-ours and graduated_a0.9 tied (p=1.0). FR-5 resolved. Holm-Bonferroni cummax bug fixed: MMLU 10/15→8/15. Cohen's d changed to d_av.\", \"bugfix_note\": \"Holm-Bonferroni cummax variable was never updated, causing 2 MMLU pairs to be incorrectly marked significant (graduated_a0.9 vs no-filter, surprisal vs dsir). Cohen's d changed from d_z to d_av (Lakens 2013).\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_E_paired_stats.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_E_paired_stats.json\", \"completed_at\": \"2026-05-15T11:20:31.718Z\", \"notes\": \"Holm-Bonferroni bug fixed: cummax variable was never updated in loop, causing adjusted p-values to lose monotonicity. MMLU significant pairs corrected 10/15→8/15. Cohen's d changed from d_z to d_av (Lakens 2013). d values still large (10.8) due to n=5 tiny within-seed variance — recommend mean_diff as primary effect size in paper.\"}, \"exp_D_obd_n500\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:18:27.182Z\", \"updated_at\": \"2026-05-15T11:46:23.600Z\", \"hypothesis\": \"OBD-LightGBM 在 N=500 子集上 accuracy 是否仍高于 LLM baselines？验证样本量匹配下的公平比较（FR-12 Warning）\", \"spec\": {\"command\": \"python scripts/exp_D_obd_n500_v2.py\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp001_pythia + artifacts/exp011_samples.jsonl\", \"data_count\": 500, \"model_name\": \"N/A (CPU: OBD-LightGBM on N=500 subset)\", \"seed\": 42, \"note\": \"Bootstrap CI for OBD accuracy on same 500 samples as LLM baseline\"}, \"conclusion\": \"success\", \"metrics\": {\"obd_accuracy_final\": 0.38, \"obd_ci\": [0.34, 0.422], \"mcnemar_vs_gpt55_p\": 0.0809, \"mcnemar_vs_claude_p\": 0.0693, \"mcnemar_significant\": false, \"multi_seed_std\": 0, \"per_depth\": {\"d0\": 0.96, \"d1\": 0.39, \"d2\": 0.14, \"d3\": 0.19, \"d4\": 0.22}, \"prob_merge_accuracy\": 0.444, \"prob_merge_d4_bias\": 0.8, \"note\": \"v2 logic (6-class argmax, no capping/merge) + seed=42. McNemar not significant — supports discussion.tex narrative\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_D_obd_n500_v2.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_D_obd_n500_v2.json\", \"completed_at\": \"2026-05-15T11:20:31.077Z\"}, \"exp_B_14d_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:18:25.666Z\", \"updated_at\": \"2026-05-15T11:20:29.596Z\", \"hypothesis\": \"移除 self_BLEU（14D vs 15D）后 K*=2 是否稳定？排除 self_BLEU information leakage（FR-3 Critical）\", \"spec\": {\"command\": \"python scripts/exp_B_14d_ablation.py\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data + data_exp001_pythia + data_exp002_olmo + data_exp017_qwen_cont\", \"data_count\": 20000, \"model_name\": \"N/A (CPU: LightGBM 14D vs 15D)\", \"seed\": 42, \"note\": \"Remove self_BLEU, compare 14D vs 15D pairwise AUC and K*\"}, \"conclusion\": \"success\", \"metrics\": {\"result\": \"K*=2 stable across all 4 models after removing self_BLEU (14D)\", \"key_finding\": \"self_BLEU removal does not change K* boundary. FR-3 resolved.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_B_14d_ablation.json\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_B_14d_ablation.json\", \"completed_at\": \"2026-05-15T11:20:29.596Z\"}, \"exp_A_alt_scorer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:18:24.715Z\", \"updated_at\": \"2026-05-15T11:19:40.861Z\", \"hypothesis\": \"替代 scorer (Pythia-1.4B, OLMo-1B) 计算 surprisal features 时，K*=2 是否仍成立？验证 K* 不依赖 scorer-generator 匹配（FR-2 Critical）\", \"spec\": {\"command\": \"bash scripts/run_exp_A.sh\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data (Qwen-RW) + data_exp017_qwen_cont (Qwen-cont)\", \"data_count\": 10000, \"model_name\": \"Pythia-1.4B + OLMo-1B (as alt scorers) × Qwen-generated data\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"note\": \"4 conditions: {Pythia,OLMo} × {Qwen-RW,Qwen-cont}. Surprisal features computed with alt scorer, LightGBM classification.\"}, \"conclusion\": \"success\", \"metrics\": {\"pythia_qwen_rw\": {\"k_star\": 2, \"auc_0v1\": 0.9923, \"auc_1v2\": 0.7012, \"auc_2v3\": 0.587, \"mae\": 1.006, \"accuracy\": 0.417, \"spearman_rho_vs_baseline\": 0.906}, \"pythia_qwen_cont\": {\"k_star\": 1, \"auc_0v1\": 0.99, \"auc_1v2\": 0.5923, \"auc_2v3\": null, \"mae\": 1.216, \"accuracy\": 0.371, \"spearman_rho_vs_baseline\": 0.942}, \"olmo_qwen_rw\": {\"k_star\": 2, \"auc_0v1\": 0.9918, \"auc_1v2\": 0.6947, \"auc_2v3\": null, \"mae\": 1.016, \"accuracy\": 0.413, \"spearman_rho_vs_baseline\": 0.92}, \"olmo_qwen_cont\": {\"k_star\": 1, \"auc_0v1\": 0.989, \"auc_1v2\": 0.5858, \"auc_2v3\": null, \"mae\": 1.229, \"accuracy\": 0.368, \"spearman_rho_vs_baseline\": 0.902}, \"key_finding\": \"K* splits by generator data, not scorer: Qwen-RW→K*=2, Qwen-cont→K*=1 (cross-scorer). Feature importance ρ≥0.90 across all 4 conditions confirms scorer independence of feature ranking.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_A/\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp_A/exp_A_alt_scorer.log\", \"completed_at\": \"2026-05-15T11:19:40.861Z\"}, \"exp_015_neural_probe\": {\"status\": \"DONE\", \"retry_count\": 3, \"created_at\": \"2026-05-13T18:53:34.791Z\", \"updated_at\": \"2026-05-15T10:47:04.883Z\", \"hypothesis\": \"Learned representations (frozen LLM → MLP) 的 K* 是否高于 hand-crafted 15D features？若 K*_neural > K*_15D，说明 15D projection 是 K*=2 的部分原因；若相同，加强 information-theoretic impossibility 论证\", \"notes\": \"v4 completed successfully. 3 models: Pythia K*_neural=2, OLMo K*_neural=2, Qwen-cont K*_neural=3. Neural probe improves 2v3 AUC across all models (Pythia +0.044, OLMo +0.039, Qwen +0.055) but only Qwen-cont self-scorer crosses θ=0.60. EXIT_CODE=129 (SIGHUP after completion) did not affect results.\", \"completed_at\": \"2026-05-14T02:58:02.023Z\", \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 26.00 MiB. GPU 0 has a total capacity of 23.52 GiB of which 20.06 MiB is free. Process 55665 has 13.36 GiB memory in use. Process 56371 has 9.09 GiB memory in use. Including non-PyTorch memory, this process has 1\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"v4 run in progress (PID 108774, tmux: exp015, westc-26893). Root cause of prior failures: v2=OOM (concurrent exp-006 占 GPU), v3=SIGHUP/EXIT_CODE=129 (SSH 断连，未在 tmux 中)。v4 在 tmux 中安全运行，Pythia 86% → OLMo → Qwen-cont → MLP training。内存管理正确 (del+gc+empty_cache)，6.7GB/24GB。ETA ~25-30min from 09:28 UTC.\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:21:59.744073+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:31:39.481148+00:00\"}]}, \"reproduce\": {\"finished_at\": \"2026-05-15T09:31:35.099Z\"}, \"conclusion\": \"success\", \"metrics\": {\"pythia\": {\"k_star_neural\": 2, \"k_star_lgbm\": 2, \"accuracy\": 0.3892, \"pairwise_auc\": {\"0v1\": 0.966, \"1v2\": 0.676, \"2v3\": 0.596, \"3v4\": 0.555, \"4v5\": 0.532}}, \"olmo\": {\"k_star_neural\": 2, \"k_star_lgbm\": 2, \"accuracy\": 0.3729, \"pairwise_auc\": {\"0v1\": 0.95, \"1v2\": 0.657, \"2v3\": 0.589, \"3v4\": 0.547, \"4v5\": 0.53}}, \"qwen_cont\": {\"k_star_neural\": 3, \"k_star_lgbm\": 2, \"accuracy\": 0.4368, \"pairwise_auc\": {\"0v1\": 0.988, \"1v2\": 0.702, \"2v3\": 0.616, \"3v4\": 0.59, \"4v5\": 0.566}}, \"key_finding\": \"Neural probe K*_neural=2 for Pythia and OLMo (same as 15D), K*_neural=3 only for Qwen-cont (self-scorer). 2v3 AUC improved in all models vs LightGBM but only Qwen-cont crosses θ=0.60. K*=2 is robust for cross-model probes.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp015_neural_probe_results.json\", \"log_path\": \"~/runs/gen-depth-contamination/exp_015_neural_probe.log\", \"spec\": {\"command\": \"python scripts/run_exp015_neural_probe.py --device cuda:0 --embed_batch_size 8\", \"server\": \"westc-26893\", \"data_path\": \"data_exp001_pythia + data_exp002_olmo + data_exp017_qwen_cont\", \"data_count\": 90000, \"model_name\": \"Qwen/Qwen2.5-1.5B-Instruct (frozen encoder -> MLP probe)\", \"seed\": \"5-fold CV\"}}, \"exp_006_graduated_filtering\": {\"status\": \"DONE\", \"retry_count\": 3, \"created_at\": \"2026-05-13T20:25:52.364Z\", \"updated_at\": \"2026-05-15T09:18:18.667Z\", \"hypothesis\": \"K*-aware graduated filtering (exploiting human/gen-1/gen-2+ trichotomy) yields better downstream LM quality than binary filtering on MMLU and HellaSwag. 6 strategies × 5 seeds × α sweep.\", \"parent\": \"exp_003_decoding_ablation\", \"notes\": \"51/51 COMPLETE. All 6 strategies × 5 seeds + base_model finished 2026-05-15 ~09:10 UTC.\\n\\nFINAL RANKING (MMLU descending):\\n1. binary-ours: 0.5941±0.0008 / 0.6701±0.0006 (BEST)\\n2. binary-drayson: 0.5913±0.0009 / 0.6691±0.0004\\n3. surprisal: 0.5894±0.0009 / 0.6641±0.0006\\n4. graduated_a0.9: 0.5892±0.0008 / 0.6701±0.0007\\n5. graduated_a0.7: 0.5892±0.0014 / 0.6695±0.0004\\n6. graduated_a0.5: 0.5880±0.0013 / 0.6687±0.0008\\n7. graduated_a0.3: 0.5877±0.0013 / 0.6669±0.0005\\n8. graduated_a0.1: 0.5873±0.0019 / 0.6640±0.0009\\n9. dsir: 0.5869±0.0003 / 0.6631±0.0007\\n10. no-filter: 0.5865±0.0010 / 0.6638±0.0008\\nBase: 0.6018 / 0.6821\\n\\nVERSION B fully confirmed. Binary-ours is optimal. Graduated α monotonic. DSIR below all strategies except no-filter.\", \"reproduce\": {\"finished_at\": \"2026-05-14T21:31:53.630Z\"}, \"failure_reason\": \"EXIT_CODE=124 (timeout — exceeded timeout_hours)\", \"completed_at\": \"2026-05-14T21:04:20.455Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:04:21.389845+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:32:00.501871+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"RESUMED 05-14 ~21:30 UTC after EXIT_CODE=124 timeout crash. 32/50 runs complete pre-crash. 18 remaining: a0.7(s456/s789/s1024) + a0.9(5) + surprisal(5) + dsir(5). Script has built-in skip logic (checks eval_results.json). Running in tmux:exp006_resume without timeout wrapper. ETA: ~05-15 11:00-12:00 UTC.\"}}, \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/gen-depth-contamination && python scripts/exp006_graduated_filtering.py\", \"server\": \"westc-26893\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/depth_corpus_30k\", \"data_count\": 30000, \"model_name\": \"Qwen2.5-1.5B-Instruct\", \"seed\": \"42,123,456,789,1024\", \"gpu\": \"cuda:0\", \"checkpoint_source\": \"Qwen/Qwen2.5-1.5B-Instruct (HuggingFace, LoRA fine-tune from base)\", \"eval_data\": \"MMLU (14042 test, 0-shot) + HellaSwag (10042 val, 0-shot) via lm-eval-harness\", \"note\": \"Resumed run. tmux: exp_006_graduated_filtering. 33/50 complete, 17 remaining. ETA ~05-15 07:30-08:30 UTC.\"}, \"conclusion\": \"success\", \"metrics\": {\"total_runs\": 51, \"binary_ours\": {\"mmlu\": \"0.5941±0.0008\", \"hellaswag\": \"0.6701±0.0006\"}, \"binary_drayson\": {\"mmlu\": \"0.5913±0.0009\", \"hellaswag\": \"0.6691±0.0004\"}, \"surprisal\": {\"mmlu\": \"0.5894±0.0009\", \"hellaswag\": \"0.6641±0.0006\"}, \"graduated_a09\": {\"mmlu\": \"0.5892±0.0008\", \"hellaswag\": \"0.6701±0.0007\"}, \"graduated_a07\": {\"mmlu\": \"0.5892±0.0014\", \"hellaswag\": \"0.6695±0.0004\"}, \"graduated_a05\": {\"mmlu\": \"0.5880±0.0013\", \"hellaswag\": \"0.6687±0.0008\"}, \"graduated_a03\": {\"mmlu\": \"0.5877±0.0013\", \"hellaswag\": \"0.6669±0.0005\"}, \"graduated_a01\": {\"mmlu\": \"0.5873±0.0019\", \"hellaswag\": \"0.6640±0.0009\"}, \"dsir\": {\"mmlu\": \"0.5869±0.0003\", \"hellaswag\": \"0.6631±0.0007\"}, \"no_filter\": {\"mmlu\": \"0.5865±0.0010\", \"hellaswag\": \"0.6638±0.0008\"}, \"base_model\": {\"mmlu\": \"0.6018\", \"hellaswag\": \"0.6821\"}, \"best_strategy\": \"binary-ours\", \"key_finding\": \"binary-ours is best filtering strategy. All strategies degrade vs base_model. Graduated α monotonically increasing confirms K*=2 boundary. DSIR below all other strategies except no-filter.\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp006_filtering/results/\", \"log_path\": \"~/runs/gen-depth-contamination/exp_006_graduated_filtering.log\"}, \"exp_007_bootstrap_ci\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T03:45:50.948Z\", \"updated_at\": \"2026-05-13T23:43:00.694Z\", \"hypothesis\": \"K* 统计严谨性验证：bootstrap 95% CI 和 permutation test 确认 K*=2 在三个模型族上统计显著\", \"spec\": {\"command\": \"python scripts/bootstrap_ci.py --data_dirs results_exp001_pythia results_exp002_olmo data --labels Pythia-1.4B OLMo-1B Qwen-1.5B --output artifacts/bootstrap_ci_results.json\", \"script_path\": \"/root/autodl-tmp/gen-depth-contamination/scripts/bootstrap_ci.py\", \"server\": \"autodl-4090d\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/bootstrap_ci_results.json\", \"data_count\": 15000, \"model_name\": \"Pythia-1.4B / OLMo-1B / Qwen-1.5B\", \"seed\": 42, \"input_sources\": [\"results_exp001_pythia (exp-001)\", \"results_exp002_olmo (exp-002)\", \"data (mvp-001)\"], \"bootstrap_resamples\": 1000, \"permutation_resamples\": 500, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/bootstrap_ci_results.json\", \"log_path\": \"~/runs/gen-depth-contamination/exp_007_bootstrap_ci.log\"}, \"metrics\": {\"qwen_rewrite\": {\"0v1\": {\"auc\": 0.9956, \"ci_lower\": 0.9946, \"ci_upper\": 0.9965, \"perm_p\": 0.002}, \"1v2\": {\"auc\": 0.6955, \"ci_lower\": 0.6859, \"ci_upper\": 0.7041, \"perm_p\": 0.002}, \"2v3\": {\"auc\": 0.5893, \"ci_lower\": 0.5795, \"ci_upper\": 0.5991, \"perm_p\": 0.002}, \"3v4\": {\"auc\": 0.5435, \"ci_lower\": 0.5333, \"ci_upper\": 0.5551, \"perm_p\": 0.002}, \"4v5\": {\"auc\": 0.534, \"ci_lower\": 0.5238, \"ci_upper\": 0.5448, \"perm_p\": 0.002}}, \"pythia_cont\": {\"0v1\": {\"auc\": 0.9932, \"ci_lower\": 0.9921, \"ci_upper\": 0.9943, \"perm_p\": 0.002}, \"1v2\": {\"auc\": 0.6539, \"ci_lower\": 0.6454, \"ci_upper\": 0.663, \"perm_p\": 0.002}, \"2v3\": {\"auc\": 0.5514, \"ci_lower\": 0.5417, \"ci_upper\": 0.5628, \"perm_p\": 0.002}, \"3v4\": {\"auc\": 0.5152, \"ci_lower\": 0.5041, \"ci_upper\": 0.526, \"perm_p\": 0.006}, \"4v5\": {\"auc\": 0.5136, \"ci_lower\": 0.5021, \"ci_upper\": 0.5249, \"perm_p\": 0.008}}, \"olmo_cont\": {\"0v1\": {\"auc\": 0.997, \"ci_lower\": 0.9964, \"ci_upper\": 0.9975, \"perm_p\": 0.002}, \"1v2\": {\"auc\": 0.6145, \"ci_lower\": 0.6045, \"ci_upper\": 0.6247, \"perm_p\": 0.002}, \"2v3\": {\"auc\": 0.5496, \"ci_lower\": 0.5399, \"ci_upper\": 0.5596, \"perm_p\": 0.002}, \"3v4\": {\"auc\": 0.5091, \"ci_lower\": 0.4973, \"ci_upper\": 0.52, \"perm_p\": 0.064}, \"4v5\": {\"auc\": 0.5045, \"ci_lower\": 0.4932, \"ci_upper\": 0.515, \"perm_p\": 0.232}}, \"qwen_cont\": {\"0v1\": {\"auc\": 0.9971, \"ci_lower\": 0.9963, \"ci_upper\": 0.9978, \"perm_p\": 0.002}, \"1v2\": {\"auc\": 0.6112, \"ci_lower\": 0.6015, \"ci_upper\": 0.6213, \"perm_p\": 0.002}, \"2v3\": {\"auc\": 0.5609, \"ci_lower\": 0.5511, \"ci_upper\": 0.5712, \"perm_p\": 0.002}, \"3v4\": {\"auc\": 0.5409, \"ci_lower\": 0.5308, \"ci_upper\": 0.5508, \"perm_p\": 0.002}, \"4v5\": {\"auc\": 0.5141, \"ci_lower\": 0.5035, \"ci_upper\": 0.5255, \"perm_p\": 0.006}}, \"k_star_robust\": true, \"all_1v2_ci_lower_above_060\": true, \"most_marginal\": \"Qwen-cont CI lower=0.6015, only 0.0015 above threshold\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T03:46:36.617Z\"}, \"exp_011_llm_zeroshot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T08:59:07.954Z\", \"updated_at\": \"2026-05-13T11:34:44.605Z\", \"hypothesis\": \"Frontier LLMs (GPT-5.5, Claude Opus 4.6) cannot reliably estimate generational depth via zero-shot prompting, motivating the need for specialized statistical methods\", \"spec\": {\"command\": \"python3 scripts/exp011_llm_zeroshot.py --model gpt-5.5 && python3 scripts/exp011_llm_zeroshot.py --model claude-opus-4-6 && python3 scripts/exp011_analyze.py\", \"server\": \"autodl-4090d\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data_exp001_pythia/\", \"data_count\": 500, \"model_name\": \"GPT-5.5 + Claude Opus 4.6 (zero-shot via OpenRouter)\", \"seed\": 42, \"sampling\": \"100 texts × 5 depths (0-4) from Pythia continuation\", \"scripts\": [\"scripts/exp011_sample_data.py\", \"scripts/exp011_llm_zeroshot.py\", \"scripts/exp011_analyze.py\"], \"samples_path\": \"artifacts/exp011_samples.jsonl\", \"api_base_url\": \"http://47.94.22.126/v1\", \"api_model_ids\": {\"gpt-5.5\": \"openai/gpt-5.5\", \"claude-opus-4-6\": \"claude-opus-4-6\"}, \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/exp011_analysis.json\", \"log_path\": \"N/A (API task)\"}, \"notes\": \"GPT-5.5: 500条, 0 parse failures. Claude Opus 4.6: 500条, 1 parse failure. 两个 frontier LLM 5-class accuracy (~33%) 均低于 OBD-LightGBM (38.6%)。Binary human/AI detection 高 (~88%) 但 fine-grained depth 判断失败。Claude proxy 需用 model ID 'claude-opus-4-6' (无 anthropic/ 前缀)。\", \"metrics\": {\"gpt55_5class_acc\": 0.332, \"gpt55_mae\": 1.102, \"gpt55_spearman\": 0.383, \"gpt55_binary_acc\": 0.878, \"claude_5class_acc\": 0.331, \"claude_mae\": 1.15, \"claude_spearman\": 0.416, \"claude_binary_acc\": 0.882, \"odb_baseline_5class_acc\": 0.386, \"odb_baseline_mae\": 1.107, \"gpt55_per_depth_acc\": {\"depth_0\": 0.77, \"depth_1\": 0.19, \"depth_2\": 0.38, \"depth_3\": 0.24, \"depth_4\": 0.08}, \"claude_per_depth_acc\": {\"depth_0\": 0.69, \"depth_1\": 0.21, \"depth_2\": 0.28, \"depth_3\": 0.101, \"depth_4\": 0.37}, \"n_samples_per_model\": 500, \"key_finding\": \"Both frontier LLMs (GPT-5.5, Claude Opus 4.6) perform WORSE than OBD-LightGBM on 5-class depth estimation (~33% vs 38.6% acc). Binary human/AI detection is high (~88%) but fine-grained depth discrimination fails.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T11:32:56.036Z\"}, \"exp_013_cross_transfer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-12T20:50:57.813Z\", \"updated_at\": \"2026-05-13T06:54:11.689Z\", \"spec\": {\"command\": \"python scripts/run_exp013_cross_transfer.py --out_dir artifacts/\", \"server\": \"autodl-4090d\", \"data_path\": \"data/, data_exp001_pythia/, data_exp002_olmo/, data_exp017_qwen_cont/\", \"data_count\": 20000, \"model_name\": \"N/A (CPU classifiers: OBD-LightGBM)\", \"seed\": 42, \"input_sources\": [\"mvp-001 Qwen-rewrite\", \"exp-001 Pythia\", \"exp-002 OLMo\", \"exp-017 Qwen-cont\"], \"checkpoint_path\": \"artifacts/cross_transfer_matrix.json\", \"log_path\": \"N/A (CPU task)\"}, \"hypothesis\": \"Depth signal 是文本固有属性还是 model self-familiarity artifact？4×4 cross-model transfer matrix 测试分类器跨模型泛化能力\", \"metrics\": {\"accuracy_matrix\": {\"Qwen_rw→Qwen_rw\": 0.4229, \"Qwen_rw→Pythia\": 0.259, \"Qwen_rw→OLMo\": 0.2653, \"Qwen_rw→Qwen_cont\": 0.3466, \"Pythia→Qwen_rw\": 0.2718, \"Pythia→Pythia\": 0.3856, \"Pythia→OLMo\": 0.3531, \"Pythia→Qwen_cont\": 0.3287, \"OLMo→Qwen_rw\": 0.2768, \"OLMo→Pythia\": 0.345, \"OLMo→OLMo\": 0.3822, \"OLMo→Qwen_cont\": 0.3244, \"Qwen_cont→Qwen_rw\": 0.344, \"Qwen_cont→Pythia\": 0.3284, \"Qwen_cont→OLMo\": 0.3112, \"Qwen_cont→Qwen_cont\": 0.3875}, \"transfer_retention_accuracy\": {\"Pythia↔OLMo\": \"91-92%\", \"Qwen_rw→Pythia/OLMo\": \"61-63%\", \"Qwen_cont↔Pythia\": \"83-85%\", \"Qwen_cont↔OLMo\": \"80-85%\"}, \"transfer_retention_tau\": {\"Pythia↔OLMo\": \"85-86%\", \"Qwen_rw→Pythia/OLMo\": \"45-50%\", \"Qwen_cont↔others\": \"68-83%\"}, \"mean_pw_auc_matrix\": {\"within_avg\": 0.6099, \"cross_avg\": 0.5905, \"0v1_cross_all_above\": 0.96}, \"key_finding\": \"depth signal ≈ 70-85% text-intrinsic + 15-30% model self-familiarity. Binary contamination detection (0v1) highly transferable (>0.96 AUC). Fine-grained depth transfer depends on model family similarity. Qwen-rewrite overfits style features; Qwen-cont transfers much better.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T06:53:07.326Z\", \"notes\": \"depth signal ≈ 70-85% text-intrinsic + 15-30% model self-familiarity. Pythia↔OLMo 91-92% retention (architecture-agnostic). Qwen-rewrite catastrophic transfer to other models (61-63%), but Qwen-cont much better (80-85%). 0v1 universally transferable (>0.96 AUC), 1v2+ transfer depends on model family. Rewrite mode overfits style features → continuation mode is canonical condition for cross-model claims.\"}, \"exp_010_ordinal_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T04:22:42.199Z\", \"updated_at\": \"2026-05-13T04:26:54.571Z\", \"hypothesis\": \"Ordinal structure improves depth classification: ordinal methods should outperform unordered multiclass on MAE\", \"spec\": {\"command\": \"python scripts/run_exp010_ordinal_comparison.py\", \"server\": \"autodl-4090d\", \"data_path\": \"data/features.csv, data_exp001_pythia/features.csv, data_exp002_olmo/features.csv\", \"data_count\": 90000, \"model_name\": \"N/A (CPU classifiers)\", \"seed\": \"N/A\", \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/gen-depth-contamination/artifacts/ordinal_comparison_results.json\"}, \"metrics\": {\"qwen_rewrite\": {\"obd_lgbm\": {\"accuracy\": 0.4229, \"mae\": 0.9836, \"tau_b\": 0.5518, \"mean_pw_auc\": 0.6214}, \"multiclass_lgbm\": {\"accuracy\": 0.4182, \"mae\": 1.0163, \"tau_b\": 0.5367, \"mean_pw_auc\": 0.6246}, \"ordinal_logreg\": {\"accuracy\": 0.3636, \"mae\": 0.9105, \"tau_b\": 0.563, \"mean_pw_auc\": 0.5022}}, \"pythia\": {\"obd_lgbm\": {\"accuracy\": 0.3856, \"mae\": 1.1072, \"tau_b\": 0.4745, \"mean_pw_auc\": 0.6055}, \"multiclass_lgbm\": {\"accuracy\": 0.3832, \"mae\": 1.1399, \"tau_b\": 0.4622, \"mean_pw_auc\": 0.6062}, \"ordinal_logreg\": {\"accuracy\": 0.3179, \"mae\": 1.022, \"tau_b\": 0.49, \"mean_pw_auc\": 0.4767}}, \"olmo\": {\"obd_lgbm\": {\"accuracy\": 0.3822, \"mae\": 1.1469, \"tau_b\": 0.4683, \"mean_pw_auc\": 0.6015}, \"multiclass_lgbm\": {\"accuracy\": 0.3685, \"mae\": 1.1813, \"tau_b\": 0.4497, \"mean_pw_auc\": 0.5974}, \"ordinal_logreg\": {\"accuracy\": 0.3265, \"mae\": 1.0352, \"tau_b\": 0.4656, \"mean_pw_auc\": 0.4859}}}, \"conclusion\": \"success\", \"notes\": \"Ordinal methods beat multiclass LightGBM on MAE across all 3 datasets. Best MAE consistently from mord LogisticAT, not OBD-LightGBM. However, ordinal_logreg has worst pairwise AUC — it reduces MAE by collapsing predictions toward the center, not by better discrimination.\", \"completed_at\": \"2026-05-13T04:26:54.571Z\"}, \"mvp_pilot_sat_v1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-12T11:09:39.193Z\", \"updated_at\": \"2026-05-12T19:25:33.763Z\", \"hypothesis\": \"递归生成文本在统计特征空间上存在可分辨的代际差异，且差异随深度呈系统性趋势（K* ≥ 3）\", \"spec\": {\"command\": \"bash /root/autodl-tmp/gen-depth-contamination/run_mvp.sh\", \"server\": \"autodl-4090d\", \"gpu\": [\"cuda:0\"], \"pid\": \"10619\", \"log_path\": \"~/runs/gen-depth-contamination/mvp_pilot_sat_v1.log\", \"submitted_at\": \"2026-05-12T16:46:33.175Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/gen-depth-contamination/data/\", \"wall_clock_seconds\": 9533.4, \"gpu_hours\": 2.65}, \"notes\": \"v2 left-padding rerun, per-fold AUC, full self-BLEU\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-12T19:25:26.538Z\", \"metrics\": {\"pairwise_auc\": {\"0v1\": 0.9956, \"1v2\": 0.6957, \"2v3\": 0.5893, \"3v4\": 0.5434, \"4v5\": 0.5343}, \"pairwise_auc_std\": {\"0v1\": 0.0005, \"1v2\": 0.0072, \"2v3\": 0.012, \"3v4\": 0.0053, \"4v5\": 0.0091}, \"pairwise_jsd\": {\"0v1\": 0.2669, \"1v2\": 0.0163, \"2v3\": 0.0069, \"3v4\": 0.0047, \"4v5\": 0.0041}, \"k_star\": 2, \"ordinal_mae\": 1.0163, \"ordinal_accuracy\": 0.4182}}}, \"count\": 164, \"total\": 164, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5152}}"
    }
  },
  "sourceToolAssistantUUID": "167e0737-73bc-4ca3-aee7-0ce649ef9109",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-23T11:01:50.391Z_

<details><summary>↩ Tool result · `toolu_01Hpd7KUTXu1ouJVYA464hi9`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\begin{figure*}[t]
5	\centering
6	\includegraphics[width=\textwidth]{figures/pipeline.pdf}
7	\caption{Generational depth estimation pipeline. Seed documents are recursively passed through a generation operator $G_\delta$ to produce a depth chain. Corpus-level statistical features are fed to the OBD-LightGBM classifier for depth prediction. (Simplified notation; see Eq.~\ref{eq:kstar} for the formal $\Kempirical$ definition.)}
8	\label{fig:pipeline}
9	\end{figure*}
10	
11	\subsection{Problem Formulation}
12	\label{sec:formulation}
13	
14	A generation operator $G_\delta$ (LLM + decoding strategy $\delta$) produces successive generations $X \to Y_1 \to \cdots \to Y_K$, where $Y_k = G_\delta(Y_{k-1})$ and $Y_0 \triangleq X$ (Figure~\ref{fig:pipeline}).
15	This sequence forms a Markov chain.
16	By the Data Processing Inequality, $I(X; Y_1) \geq I(X; Y_2) \geq \cdots \geq 0$: mutual information with the seed text degrades monotonically.
17	Together with Markov chain convergence, this motivates the existence of a finite discrimination boundary where $\auc_{k-1,k}$ falls below a decision threshold, though AUC and mutual information are not formally equivalent; the actual saturation depth must therefore be measured empirically.
18	Pairwise AUC may exhibit non-monotonicity at deeper depths due to classifier and feature interactions (e.g., Pythia-1.4B greedy 4v5 $\auc = 1.0$ vs.\ 3v4 $= 0.522$; Table~\ref{tab:s10_pythia_decoding}), reinforcing that $\Kempirical$ is a measured quantity rather than a theoretical prediction.
19	
20	We define the operational lower bound:
21	\begin{equation}
22	  \Kempirical = \max\!\bigl\{k \!\geq\! 1 : \auc_{j-1,j} > \theta,\;\forall\, 1 \!\leq\! j \!\leq\! k\bigr\},
23	  \label{eq:kstar}
24	\end{equation}
25	which requires all pairs up to depth $k$ to exceed the threshold (the $\forall j$ constraint is naturally satisfied because $\auc_{k-1,k}$ decreases monotonically above $\theta$ across all tested configurations; Table~\ref{tab:kstar_ci}).
26	The theoretical upper bound $\Ktheory$ (the true maximum discriminable depth given optimal features) is not directly estimated in this work.
27	Since any specific classifier on a feature subset achieves AUC at most equal to the Bayes-optimal classifier on all features, $\Kempirical \leq \Ktheory$ follows directly.
28	The DPI motivates the empirical observation that $\auc_{k-1,k}$ generally decreases with $k$ under non-degenerate decoding, though AUC is not a monotone function of MI (as noted above).
29	Here $\auc_{k-1,k}$ is the point-estimate pairwise AUC and $\theta = 0.60$ is a reference operating point motivated by Cohen's small-effect-size convention ($h \approx 0.20$\footnote{Cohen's $h = 2\arcsin\!\sqrt{0.60} - 2\arcsin\!\sqrt{0.50} \approx 0.2014$ (small effect for proportions); the equivalent $d = \sqrt{2}\,\Phi^{-1}\!(0.60) \approx 0.36$ places $\theta$ in the small-to-medium range on Cohen's $d$ scale.}; justified below).
30	All pairwise significance tests use 10{,}000-iteration permutation tests with Bonferroni correction for 10 comparisons ($\alpha_{\text{corrected}}{=}0.005$); we report bootstrap 95\% CIs (1{,}000 resamples unless otherwise noted) for all boundary-pair AUCs and explicitly mark marginal cases where Bonferroni-corrected lower bounds fall below $\theta$ (Section~\ref{sec:kstar_boundary}).
31	
32	\paragraph{Threshold justification.}
33	$\theta{=}0.60$ is a reference operating point supported by three independent lines of evidence.
34	First, Cohen's $h \approx 0.20$, a conventional small-effect-size boundary.
35	Second, a 10{,}000-iteration permutation test yields a 95th-percentile null of ${<}\,0.55$ ($p < 0.002$ for all boundary comparisons).
36	Third, the conclusion $\Kempirical{=}2$ is insensitive to the exact threshold: 1v2 AUC values cluster at $0.61$--$0.70$ while 2v3 values cluster at $0.55$--$0.59$, a ${\sim}$5--11\,pp discontinuity; only at extremes does $\Kempirical$ shift ($\theta{=}0.55$: $\Kempirical{=}3$ for two Qwen configurations; $\theta{=}0.70$: $\Kempirical{=}1$ across all).
37	Figure~\ref{fig:kstar_theta} provides the full sensitivity surface across $\theta \in [0.55, 0.70]$, enabling practitioners to select $\theta$ according to their false-positive tolerance.
38	The downstream filtering evaluation (Section~\ref{sec:filtering}) uses the OBD classifier without re-optimizing $\theta$, avoiding circularity.
39	
40	\subsection{Features and Classifier}
41	\label{sec:features}
42	
43	Each document is characterized by a 15-dimensional feature vector spanning four groups: \emph{surprisal moments} (mean, std, skewness, kurtosis; 4~dims), \emph{surprisal derivatives} (mean and std of first- and second-order differences, plus first-order skewness; 5~dims), \emph{vocabulary diversity} (type-token ratio, hapax legomena ratio, self-BLEU; 3~dims), and \emph{frequency tail statistics} (frequency kurtosis, entropy, rare token fraction; 3~dims).
44	All features are computed from token-level surprisal values via an external scorer model (full definitions in Table~\ref{tab:s5_features}, Appendix).
45	Self-BLEU reference sets are drawn exclusively within each fold to prevent information leakage across cross-validation splits; self-BLEU ranks \#1 in 1/8 conditions (greedy decoding) but is absent from the top-3 in all 7 others.
46	Removing self-BLEU reduces mean $\auc_{1v2}$ by $< 1$\,pp across all models (14D $\Kempirical = 2$ for all 4 configurations); in deployment where reference corpora are unavailable, self-BLEU can be replaced with corpus-level self-similarity or omitted entirely, leaving 14 features (surprisal statistics, TTR, hapax ratio, frequency tail) that require no external reference and retain full $\Kempirical$.
47	These features are generator-agnostic in that they require no knowledge of or access to the generating model, though they depend on an external scorer for surprisal computation (Section~\ref{sec:transfer}).
48	
49	We use \emph{Ordinal Binary Decomposition} (OBD), decomposing the $(K{+}1)$-class problem into $K$ cumulative binary sub-classifiers, each estimating $P(\text{depth} > k \mid \mathbf{x})$ via LightGBM (hyperparameters in Table~\ref{tab:s6_lgbm_params}).
50	OBD achieves lower MAE than multiclass LightGBM (e.g., 0.984 vs.\ 1.016 on Qwen-rewrite) while maintaining superior pairwise $\auc$ (mean 0.6095 vs.\ 0.4883 for ordinal logistic regression).
51	
52	\subsection{Experimental Setup}
53	\label{sec:experimental_setup}
54	
55	We evaluate six primary configurations spanning three model families (Table~\ref{tab:setup}): Qwen2.5-1.5B-Instruct (rewrite and continuation), Qwen2.5-1.5B (base), Qwen2.5-7B, Pythia-1.4B, and OLMo-1B; four additional models are introduced in Section~\ref{sec:experiments}.
56	Each uses 5{,}000 C4 seeds truncated to 256 tokens, recursively generated for $K{=}5$ iterations (30{,}000 documents per configuration).
57	Default decoding: nucleus $p{=}0.95$, $T{=}1.0$; decoding ablation covers greedy, $T{=}0.7$, and $T{=}1.2$.
58	Continuation mode truncates seeds to 128 tokens and extends to 256; rewrite mode paraphrases the full text.
59	Evaluation: 5-fold GroupKFold cross-validation grouped by seed document; pairwise $\auc$ as primary metric.
60	
61	\begin{table}[t]
62	\centering
63	\small
64	\caption{Experimental configurations for depth-chain generation. \textbf{Config}: shorthand identifier; \textbf{Model}: architecture and parameter count; \textbf{Mode}: generation strategy (continuation or rewrite); $N$: number of seed documents per depth level.}
65	\label{tab:setup}
66	\begin{tabular}{llcc}
67	\toprule
68	\textbf{Config} & \textbf{Model} & \textbf{Mode} & $N$ \\
69	\midrule
70	Qwen-rw   & Qwen2.5-1.5B-Instruct & Rewrite & 5{,}000 \\
71	Qwen-cont & Qwen2.5-1.5B-Instruct & Continuation & 5{,}000 \\
72	Qwen-base & Qwen2.5-1.5B          & Continuation & 5{,}000 \\
73	Pythia    & Pythia-1.4B            & Continuation & 5{,}000 \\
74	OLMo      & OLMo-1B               & Continuation & 5{,}000 \\
75	Qwen-7B   & Qwen2.5-7B            & Continuation & 5{,}000 \\
76	\bottomrule
77	\end{tabular}
78	\end{table}
79	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "de8ab475-ecc8-4237-baa6-c75a52d01335",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "04650589-23d7-4cbb-b1dc-77bffe05da0a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/pipeline.pdf}\n\\caption{Generational depth estimation pipeline. Seed documents are recursively passed through a generation operator $G_\\delta$ to produce a depth chain. Corpus-level statistical features are fed to the OBD-LightGBM classifier for depth prediction. (Simplified notation; see Eq.~\\ref{eq:kstar} for the formal $\\Kempirical$ definition.)}\n\\label{fig:pipeline}\n\\end{figure*}\n\n\\subsection{Problem Formulation}\n\\label{sec:formulation}\n\nA generation operator $G_\\delta$ (LLM + decoding strategy $\\delta$) produces successive generations $X \\to Y_1 \\to \\cdots \\to Y_K$, where $Y_k = G_\\delta(Y_{k-1})$ and $Y_0 \\triangleq X$ (Figure~\\ref{fig:pipeline}).\nThis sequence forms a Markov chain.\nBy the Data Processing Inequality, $I(X; Y_1) \\geq I(X; Y_2) \\geq \\cdots \\geq 0$: mutual information with the seed text degrades monotonically.\nTogether with Markov chain convergence, this motivates the existence of a finite discrimination boundary where $\\auc_{k-1,k}$ falls below a decision threshold, though AUC and mutual information are not formally equivalent; the actual saturation depth must therefore be measured empirically.\nPairwise AUC may exhibit non-monotonicity at deeper depths due to classifier and feature interactions (e.g., Pythia-1.4B greedy 4v5 $\\auc = 1.0$ vs.\\ 3v4 $= 0.522$; Table~\\ref{tab:s10_pythia_decoding}), reinforcing that $\\Kempirical$ is a measured quantity rather than a theoretical prediction.\n\nWe define the operational lower bound:\n\\begin{equation}\n  \\Kempirical = \\max\\!\\bigl\\{k \\!\\geq\\! 1 : \\auc_{j-1,j} > \\theta,\\;\\forall\\, 1 \\!\\leq\\! j \\!\\leq\\! k\\bigr\\},\n  \\label{eq:kstar}\n\\end{equation}\nwhich requires all pairs up to depth $k$ to exceed the threshold (the $\\forall j$ constraint is naturally satisfied because $\\auc_{k-1,k}$ decreases monotonically above $\\theta$ across all tested configurations; Table~\\ref{tab:kstar_ci}).\nThe theoretical upper bound $\\Ktheory$ (the true maximum discriminable depth given optimal features) is not directly estimated in this work.\nSince any specific classifier on a feature subset achieves AUC at most equal to the Bayes-optimal classifier on all features, $\\Kempirical \\leq \\Ktheory$ follows directly.\nThe DPI motivates the empirical observation that $\\auc_{k-1,k}$ generally decreases with $k$ under non-degenerate decoding, though AUC is not a monotone function of MI (as noted above).\nHere $\\auc_{k-1,k}$ is the point-estimate pairwise AUC and $\\theta = 0.60$ is a reference operating point motivated by Cohen's small-effect-size convention ($h \\approx 0.20$\\footnote{Cohen's $h = 2\\arcsin\\!\\sqrt{0.60} - 2\\arcsin\\!\\sqrt{0.50} \\approx 0.2014$ (small effect for proportions); the equivalent $d = \\sqrt{2}\\,\\Phi^{-1}\\!(0.60) \\approx 0.36$ places $\\theta$ in the small-to-medium range on Cohen's $d$ scale.}; justified below).\nAll pairwise significance tests use 10{,}000-iteration permutation tests with Bonferroni correction for 10 comparisons ($\\alpha_{\\text{corrected}}{=}0.005$); we report bootstrap 95\\% CIs (1{,}000 resamples unless otherwise noted) for all boundary-pair AUCs and explicitly mark marginal cases where Bonferroni-corrected lower bounds fall below $\\theta$ (Section~\\ref{sec:kstar_boundary}).\n\n\\paragraph{Threshold justification.}\n$\\theta{=}0.60$ is a reference operating point supported by three independent lines of evidence.\nFirst, Cohen's $h \\approx 0.20$, a conventional small-effect-size boundary.\nSecond, a 10{,}000-iteration permutation test yields a 95th-percentile null of ${<}\\,0.55$ ($p < 0.002$ for all boundary comparisons).\nThird, the conclusion $\\Kempirical{=}2$ is insensitive to the exact threshold: 1v2 AUC values cluster at $0.61$--$0.70$ while 2v3 values cluster at $0.55$--$0.59$, a ${\\sim}$5--11\\,pp discontinuity; only at extremes does $\\Kempirical$ shift ($\\theta{=}0.55$: $\\Kempirical{=}3$ for two Qwen configurations; $\\theta{=}0.70$: $\\Kempirical{=}1$ across all).\nFigure~\\ref{fig:kstar_theta} provides the full sensitivity surface across $\\theta \\in [0.55, 0.70]$, enabling practitioners to select $\\theta$ according to their false-positive tolerance.\nThe downstream filtering evaluation (Section~\\ref{sec:filtering}) uses the OBD classifier without re-optimizing $\\theta$, avoiding circularity.\n\n\\subsection{Features and Classifier}\n\\label{sec:features}\n\nEach document is characterized by a 15-dimensional feature vector spanning four groups: \\emph{surprisal moments} (mean, std, skewness, kurtosis; 4~dims), \\emph{surprisal derivatives} (mean and std of first- and second-order differences, plus first-order skewness; 5~dims), \\emph{vocabulary diversity} (type-token ratio, hapax legomena ratio, self-BLEU; 3~dims), and \\emph{frequency tail statistics} (frequency kurtosis, entropy, rare token fraction; 3~dims).\nAll features are computed from token-level surprisal values via an external scorer model (full definitions in Table~\\ref{tab:s5_features}, Appendix).\nSelf-BLEU reference sets are drawn exclusively within each fold to prevent information leakage across cross-validation splits; self-BLEU ranks \\#1 in 1/8 conditions (greedy decoding) but is absent from the top-3 in all 7 others.\nRemoving self-BLEU reduces mean $\\auc_{1v2}$ by $< 1$\\,pp across all models (14D $\\Kempirical = 2$ for all 4 configurations); in deployment where reference corpora are unavailable, self-BLEU can be replaced with corpus-level self-similarity or omitted entirely, leaving 14 features (surprisal statistics, TTR, hapax ratio, frequency tail) that require no external reference and retain full $\\Kempirical$.\nThese features are generator-agnostic in that they require no knowledge of or access to the generating model, though they depend on an external scorer for surprisal computation (Section~\\ref{sec:transfer}).\n\nWe use \\emph{Ordinal Binary Decomposition} (OBD), decomposing the $(K{+}1)$-class problem into $K$ cumulative binary sub-classifiers, each estimating $P(\\text{depth} > k \\mid \\mathbf{x})$ via LightGBM (hyperparameters in Table~\\ref{tab:s6_lgbm_params}).\nOBD achieves lower MAE than multiclass LightGBM (e.g., 0.984 vs.\\ 1.016 on Qwen-rewrite) while maintaining superior pairwise $\\auc$ (mean 0.6095 vs.\\ 0.4883 for ordinal logistic regression).\n\n\\subsection{Experimental Setup}\n\\label{sec:experimental_setup}\n\nWe evaluate six primary configurations spanning three model families (Table~\\ref{tab:setup}): Qwen2.5-1.5B-Instruct (rewrite and continuation), Qwen2.5-1.5B (base), Qwen2.5-7B, Pythia-1.4B, and OLMo-1B; four additional models are introduced in Section~\\ref{sec:experiments}.\nEach uses 5{,}000 C4 seeds truncated to 256 tokens, recursively generated for $K{=}5$ iterations (30{,}000 documents per configuration).\nDefault decoding: nucleus $p{=}0.95$, $T{=}1.0$; decoding ablation covers greedy, $T{=}0.7$, and $T{=}1.2$.\nContinuation mode truncates seeds to 128 tokens and extends to 256; rewrite mode paraphrases the full text.\nEvaluation: 5-fold GroupKFold cross-validation grouped by seed document; pairwise $\\auc$ as primary metric.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Experimental configurations for depth-chain generation. \\textbf{Config}: shorthand identifier; \\textbf{Model}: architecture and parameter count; \\textbf{Mode}: generation strategy (continuation or rewrite); $N$: number of seed documents per depth level.}\n\\label{tab:setup}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Config} & \\textbf{Model} & \\textbf{Mode} & $N$ \\\\\n\\midrule\nQwen-rw   & Qwen2.5-1.5B-Instruct & Rewrite & 5{,}000 \\\\\nQwen-cont & Qwen2.5-1.5B-Instruct & Continuation & 5{,}000 \\\\\nQwen-base & Qwen2.5-1.5B          & Continuation & 5{,}000 \\\\\nPythia    & Pythia-1.4B            & Continuation & 5{,}000 \\\\\nOLMo      & OLMo-1B               & Continuation & 5{,}000 \\\\\nQwen-7B   & Qwen2.5-7B            & Continuation & 5{,}000 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n",
      "numLines": 79,
      "startLine": 1,
      "totalLines": 79
    }
  },
  "sourceToolAssistantUUID": "de8ab475-ecc8-4237-baa6-c75a52d01335",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-23T11:01:49.682Z_

<details open><summary>🔧 Tool call — Read · `toolu_012kwGTYqRxDJxtM19hob3hw`</summary>

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
  "parentUuid": "8d8092e5-b9bd-4fc6-871b-488a666bc6d9",
  "isSidechain": false,
  "requestId": "req_011CbKPP5Pf1zgmH6Q6m6bZ1",
  "type": "assistant",
  "uuid": "53e0e500-a8f7-49f4-9f15-6c2e29e59627",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RH1Vc9duTAip2PnkbYXraS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 464,
      "cache_read_input_tokens": 24153,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 350,
          "cache_read_input_tokens": 24153,
          "cache_creation_input_tokens": 464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 464
          },
          "type": "message"
        }
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

_source line 16 · 2026-05-23T11:01:49.692Z_

<details><summary>↩ Tool result · `toolu_012kwGTYqRxDJxtM19hob3hw`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate generational depth estimation on ten model configurations spanning six architecture families:
5	Pythia-1.4B, Pythia-6.9B, OLMo-1B, Qwen2.5-1.5B-Instruct (rewrite and continuation), Qwen2.5-1.5B (base), Qwen2.5-7B, LLaMA-3.1-8B, Mistral-7B, and Gemma-2-2B, all in continuation mode except where noted.
6	All experiments use the OBD-LightGBM classifier with the 15-dimensional feature set (Section~\ref{sec:method}), with 5{,}000 texts per depth level (generations 0--5).
7	
8	%% ====================================================================
9	\subsection{$\Kempirical \leq 2$ Across Model Configurations (C4)}
10	\label{sec:kstar_boundary}
11	
12	\begin{table*}[t]
13	\centering
14	\small
15	\caption{Pairwise $\auc$ for adjacent depth pairs with bootstrap 95\% CIs and permutation $p$-values for boundary rows.
16	$\Kempirical = 2$ requires 1v2 $\auc > \theta{=}0.60$ and 2v3 $\auc < \theta$; CIs quantify boundary uncertainty.
17	Extended results (all models) in Table~\ref{tab:kstar_ci_extended}.}
18	\label{tab:kstar_ci}
19	\resizebox{\textwidth}{!}{%
20	\begin{tabular}{lcccccccccc}
21	\toprule
22	 & \multicolumn{2}{c}{Qwen-rw} & \multicolumn{2}{c}{Pythia} & \multicolumn{2}{c}{OLMo} & \multicolumn{2}{c}{Qwen-cont} & \multicolumn{2}{c}{Qwen-7B\rlap{$^\ddagger$}} \\
23	\cmidrule(lr){2-3}\cmidrule(lr){4-5}\cmidrule(lr){6-7}\cmidrule(lr){8-9}\cmidrule(lr){10-11}
24	 & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI \\
25	\midrule
26	0v1 & .9956 & & .9722 & & .9860 & & .9971 & & .9638 & [.961,\,.967] \\
27	1v2 & .6955 & [.686,\,.704]\rlap{$^*$} & .6074 & [.598,\,.617]\rlap{$^*$} & .5001 & [.496,\,.519] & .6112 & [.602,\,.621]\rlap{$^*$} & .6168 & [.608,\,.626]\rlap{$^*$} \\
28	2v3 & .5893 & [.580,\,.599] & .5440 & [.534,\,.554] & .4973 & [.486,\,.509] & .5609 & [.551,\,.571] & .5492 & [.539,\,.559] \\
29	3v4 & .5435 & & .5051 & & .5024\rlap{$^\S$} & & .5409 & & .5276 & \\
30	4v5 & .5340 & & .5079 & & .4942 & & .5141 & & .5085 & \\
31	\bottomrule
32	\multicolumn{11}{l}{\footnotesize $^*$Permutation $p < 0.001$ for all starred boundary comparisons ($\auc > \theta$).} \\
33	\multicolumn{11}{l}{\footnotesize $^\ddagger$Generator: Qwen2.5-7B (fp16); scorer: Qwen2.5-1.5B.} \\
34	\multicolumn{11}{l}{\footnotesize $^\S$OLMo 2v3 (0.497) $<$ 3v4 (0.502): non-monotonic reversal within noise ($\Delta = 0.005$).} \\
35	\multicolumn{11}{l}{\footnotesize Full results for all 10 configurations (including LLaMA-8B, Mistral-7B, Qwen-base, Gemma-2-2B, and Pythia-6.9B) in Table~\ref{tab:kstar_ci_extended}.}
36	\end{tabular}}
37	\end{table*}
38	
39	\begin{figure}[t]
40	\centering
41	\includegraphics[width=\columnwidth]{figures/fig2_auc_decay.pdf}
42	\caption{Pairwise $\auc$ decay across adjacent depth pairs (0v1, 1v2, \ldots, 4v5) for model-mode configurations (solid) and decoding strategies (dashed); shaded bands show bootstrap 95\% confidence intervals. The horizontal dashed line marks $\theta = 0.60$.}
43	\label{fig:auc_decay}
44	\end{figure}
45	
46	Table~\ref{tab:kstar_ci} and Figure~\ref{fig:auc_decay} show $\Kempirical \leq 2$ across all 10 configurations: 6/10 yield $\Kempirical{=}2$ (Qwen$\times$4, LLaMA-8B, Pythia-1.4B; 1v2 $\auc$: 0.607--0.696; $p < 0.001$), while OLMo-1B, Mistral-7B, Pythia-6.9B, and Gemma-2-2B yield $\Kempirical{=}1$ (1v2 $\auc$: 0.500--0.598; Section~\ref{sec:boundary_cases}).
47	Under Bonferroni correction (99.5\% CIs), three of six $\Kempirical{=}2$ configurations retain significance; the three marginal cases (Pythia-1.4B, Qwen-cont, LLaMA-8B; CI lower bounds 0.593--0.599) reflect narrow effect sizes rather than classification failure.
48	By architecture family: Qwen (4/4) and LLaMA (1/1) yield $\Kempirical{\geq}2$ at nominal significance; OLMo (1/1), Mistral (1/1), and Gemma (1/1) yield $\Kempirical{=}1$; Pythia exhibits a scale-dependent split (1.4B: $\Kempirical{=}2$, 6.9B: $\Kempirical{=}1$).
49	LLaMA-3.1-8B confirms $\Kempirical{=}2$ (0v1 $\auc = 0.9225$, 1v2 $\auc = 0.6123\;[0.603,\,0.622]$; CI lower bound above $\theta$; Table~\ref{tab:kstar_ci_extended}).
50	All four decoding strategies likewise yield $\Kempirical{=}2$ (Table~\ref{tab:s2_decoding}).
51	The 1v2 spread due to generation mode ($\Delta = 8.4$\,pp within Qwen) exceeds the spread across $\Kempirical{=}2$ continuation models ($\Delta = 1.9$\,pp).
52	
53	\paragraph{Scale and instruction-tuning invariance.}
54	$\Kempirical{=}2$ persists from 1.5B through 8B: Qwen-7B (1v2 $\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\auc = 0.6123$) both exceed $\theta$, despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\ $> 0.99$ at $\leq$1.5B).
55	A base-vs.-instruct ablation at 1.5B likewise yields $\Kempirical = 2$ (1v2 $\auc = 0.626$), confirming the boundary is not an instruction-tuning artifact.
56	
57	\begin{figure*}[t]
58	\centering
59	\includegraphics[width=0.75\textwidth]{figures/fig_kstar_theta.pdf}
60	\caption{$\Kempirical(\theta)$ sensitivity curve for five configurations. $\Kempirical$: maximum discriminable depth; $\theta$: AUC decision threshold. Four of five configurations yield $\Kempirical{=}2$ at $\theta{=}0.60$ (dashed line); OLMo yields $\Kempirical{=}1$. At $\theta{=}0.70$, all drop to $\Kempirical{=}1$.}
61	\label{fig:kstar_theta}
62	\end{figure*}
63	
64	Figure~\ref{fig:kstar_theta} displays the sensitivity surface across $\theta \in [0.55, 0.70]$: four of five configurations shown yield $\Kempirical = 2$ within $\theta \in [0.51, 0.61]$ (OLMo: $\Kempirical = 1$ throughout); at $\theta{=}0.55$, two Qwen configurations reach $\Kempirical = 3$; at $\theta{=}0.70$, all drop to $\Kempirical = 1$.
65	
66	%% ====================================================================
67	\subsection{Cross-Model Transfer}
68	\label{sec:transfer}
69	
70	\begin{figure}[t]
71	\centering
72	\includegraphics[width=\columnwidth]{figures/fig3_transfer_heatmap.pdf}
73	\caption{Cross-model transfer heatmap (continuation-mode models). Each cell shows 6-class ordinal accuracy when trained on the row model and tested on the column model, divided by in-domain accuracy (retention rate). Pythia$\leftrightarrow$OLMo: 90--92\%.}
74	\label{fig:transfer_heatmap}
75	\end{figure}
76	
77	Continuation-mode classifiers transfer well across generators (Figure~\ref{fig:transfer_heatmap}; full matrix in Table~\ref{tab:s1_transfer}): Pythia$\leftrightarrow$OLMo retains 90--92\%, Qwen-cont$\leftrightarrow$Pythia 84--85\%, Qwen-cont$\leftrightarrow$OLMo 80--85\% (0v1 cross-model $\auc > 0.96$ for all pairs).
78	Qwen-rewrite classifiers transfer poorly (61--63\%), confirming reliance on mode-specific artifacts rather than generalizable depth features.
79	
80	\paragraph{Cross-scorer validation.}
81	Replacing the self-scorer with Pythia-1.4B or OLMo-1B preserves feature rankings ($\rho > 0.90$) but attenuates absolute discriminability at the boundary (Table~\ref{tab:crossscorer}).
82	Feature ranking independence is a strong result: the same features dominate under all scorers.
83	$\Kempirical$ agreement, however, is signal-strength dependent: Qwen-rewrite (strong signal, 1v2 $\auc = 0.696$) retains $\Kempirical{=}2$ under all scorers, but Qwen-continuation (marginal, 1v2 $\auc = 0.611$, only 0.011 above $\theta$) drops to $\Kempirical{=}1$ (Pythia: $0.5923$; OLMo: $0.5858$).
84	A three-way ANOVA (Generator $\times$ Scorer $\times$ Depth-Pair; Table~\ref{tab:anova_crossscorer}) confirms a statistically significant but modest Scorer main effect ($\eta^2_p{=}.166$, $p < .001$) and a significant Generator$\times$Scorer interaction ($\eta^2_p{=}.146$), indicating that absolute AUC values are scorer-dependent even when $\Kempirical$ classifications largely agree.
85	
86	%% ====================================================================
87	\subsection{Feature Ordering and Generation Mode}
88	\label{sec:feature_degradation}
89	\label{sec:generation_mode}
90	
91	Among continuation-mode models, single-feature $\auc$ rankings are highly correlated ($\rho \geq 0.85$; Table~\ref{tab:top_features}).
92	The top-3 features (\texttt{surp\_d1\_std}, \texttt{surp\_std}, \texttt{surp\_d2\_std}) are shared across all three families, revealing that autoregressive generation progressively damps surprisal variability.
93	Qwen-rewrite diverges (\texttt{freq\_entropy} dominates), consistent with its poor cross-model transfer (61--63\%).
94	Within Qwen, rewrite yields 1v2 $\auc = 0.6955$ vs.\ continuation's $0.6112$ ($\Delta = +8.4$\,pp); continuation mode is therefore recommended as the canonical condition.
95	
96	%% ====================================================================
97	\subsection{Neural Probe}
98	\label{sec:neural_probe}
99	
100	Replacing the 15D features with frozen encoder hidden states (MLP probe; Table~\ref{tab:neural_probe_crossmodel}), Qwen achieves $\Kempirical^{\text{neural}} = 3$ (2v3 $\auc = 0.6159$), while Pythia remains at $\Kempirical^{\text{neural}} = 2$ ($\auc_{2v3} = 0.5963$); OLMo yields $\Kempirical^{\text{neural}} = 1$ (1v2 $\auc = 0.5054$, consistent with its 15D boundary).
101	We hypothesize that the Qwen-only elevation reflects self-familiarity artifacts, consistent with the poor transfer observed in Section~\ref{sec:transfer}; the 15D features yield $\Kempirical = 2$ for most families (OLMo: $\Kempirical = 1$).
102	
103	\noindent\begin{minipage}{\columnwidth}
104	\centering
105	\footnotesize
106	\captionof{table}{Neural probe pairwise AUC using frozen-encoder MLP. Each cell reports AUC for classifying depth $d$ vs.\ $d{+}1$ text. $\Kempirical^{\text{neural}}$: maximum depth where AUC exceeds $\theta = 0.60$.}
107	\label{tab:neural_probe_crossmodel}
108	\resizebox{\columnwidth}{!}{%
109	\begin{tabular}{lccc}
110	\toprule
111	\textbf{Model} & \textbf{2v3 $\auc$} & \textbf{95\% CI} & $\Kempirical^{\text{neural}}$ \\
112	\midrule
113	Qwen-1.5B  & 0.6159 & $[0.610,\,0.622]$ & 3 \\
114	Pythia-1.4B & 0.5963 & $[0.589,\,0.603]$ & 2 \\
115	OLMo-1B    & 0.5056 & $[0.497,\,0.516]$ & 1\rlap{$^\dagger$} \\
116	\bottomrule
117	\multicolumn{4}{l}{\footnotesize $^\dagger$OLMo 1v2 $\auc = 0.5054$ (below $\theta$); $\Kempirical^{\text{neural}} = 1$.}
118	\end{tabular}}
119	\end{minipage}
120	
121	%% ====================================================================
122	\subsection{Cross-Domain Variation}
123	\label{sec:cross_domain}
124	
125	The preceding experiments use C4 (general web text).
126	To test domain dependence, we evaluate on Wikipedia ($n{=}5{,}000$) and arXiv abstracts ($n{=}2{,}200$) across three architecture families.
127	Wikipedia yields $\Kempirical{=}2$ (1v2 $\auc = 0.619$, 2v3 $\auc = 0.550$; Table~\ref{tab:domain_kstar}), matching the C4 baseline.
128	Qwen-1.5B, Pythia-1.4B, and LLaMA-3.1-8B yield $\Kempirical{=}3$ for arXiv (Table~\ref{tab:domain_kstar}): 2v3 $\auc = 0.644\;[0.628,\,0.658]$, $0.655\;[0.640,\,0.669]$, and $0.620\;[0.605,\,0.635]$ respectively (bootstrap CI lower bounds above $\theta$; permutation $p < 0.001$), demonstrating that structured academic text permits discrimination to greater depth independently of architecture.
129	The elevated signal reflects higher per-generation distributional shift (1v2 JSD $= 0.077$ vs.\ ${\sim}0.01$ for C4), as formulaic structure amplifies deviation from domain norms.
130	We additionally evaluate on CodeSearchNet Python ($n{=}5{,}000$, continuation mode); all four tested models (Qwen-1.5B, Qwen-7B, LLaMA-8B, Mistral-7B) yield $\Kempirical{=}2$ (Table~\ref{tab:domain_kstar}), matching the C4 baseline.
131	
132	\begin{table}[t]
133	\centering
134	\footnotesize
135	\caption{Cross-domain $\Kempirical$ comparison. $\Kempirical{=}2$ for C4, Wikipedia, and Code; $\Kempirical{=}3$ for arXiv (three families confirmed in text; representative rows shown).}
136	\label{tab:domain_kstar}
137	\resizebox{\columnwidth}{!}{%
138	\begin{tabular}{llccc}
139	\toprule
140	\textbf{Domain} & \textbf{Model} & \textbf{1v2 $\auc$} & \textbf{2v3 $\auc$} & $\Kempirical$ \\
141	\midrule
142	arXiv & Qwen-1.5B\rlap{$^\dagger$}  & .858 & .644 & 3 \\
143	arXiv & Pythia-1.4B & .805 & .655 & 3 \\
144	C4    & Qwen-1.5B\rlap{$^\dagger$}  & .626 & .550 & 2 \\
145	Wiki  & Qwen-1.5B\rlap{$^\dagger$}  & .619 & .550 & 2 \\
146	Code  & Qwen-1.5B\rlap{$^\dagger$}  & .738 & .530 & 2 \\
147	Code  & LLaMA-8B   & .739 & .510 & 2 \\
148	\bottomrule
149	\multicolumn{5}{l}{\footnotesize $^\dagger$Qwen2.5-1.5B (base, continuation mode).}
150	\end{tabular}}
151	\end{table}
152	
153	\paragraph{Robustness.}
154	\label{sec:robustness}
155	$\Kempirical{=}2$ holds across segment lengths of 128, 256, and 512 tokens (Table~\ref{tab:s11_length_ablation}); at 512 tokens the 1v2 CI lower bound falls marginally below $\theta$ but 2v3 remains well below $\theta$ at all lengths ($\leq 0.572$).
156	Seed robustness testing (seed $= 123$ vs.\ primary $= 42$; Table~\ref{tab:seed_robustness}) confirms $\Kempirical$ stability in 2/3 configurations; the one marginal shift (Qwen-Wikipedia $\Kempirical{=}2 \to 3$, 2v3 $\auc = 0.607$) has one of five folds below $\theta$.
157	The ${\pm}9$\,pp absolute AUC variation across seeds strengthens the case for threshold-based $\Kempirical$ over raw AUC comparisons.
158	
159	%% ====================================================================
160	\subsection{Binary Detector Confidence}
161	\label{sec:binary_confidence}
162	
163	Binary detectors (DivEye~\cite{basani2026diveye}, Binoculars~\cite{hans2024binoculars}) remain effective for human-vs.-machine classification but provide no usable depth signal beyond this binary boundary.
164	Pairwise $\auc$ yields $\Kempirical^{\text{binary}} \leq 1$; moderate rank correlations with depth ($|\rho| = 0.06$--$0.46$; Table~\ref{tab:s9_binary_spearman}) are driven entirely by the 0v1 gap rather than fine-grained depth discrimination, and multiple conditions exhibit non-monotonic AUC at deeper pairs.
165	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "53e0e500-a8f7-49f4-9f15-6c2e29e59627",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "8c67ad03-ec6a-417c-9adb-8e135e916145",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe evaluate generational depth estimation on ten model configurations spanning six architecture families:\nPythia-1.4B, Pythia-6.9B, OLMo-1B, Qwen2.5-1.5B-Instruct (rewrite and continuation), Qwen2.5-1.5B (base), Qwen2.5-7B, LLaMA-3.1-8B, Mistral-7B, and Gemma-2-2B, all in continuation mode except where noted.\nAll experiments use the OBD-LightGBM classifier with the 15-dimensional feature set (Section~\\ref{sec:method}), with 5{,}000 texts per depth level (generations 0--5).\n\n%% ====================================================================\n\\subsection{$\\Kempirical \\leq 2$ Across Model Configurations (C4)}\n\\label{sec:kstar_boundary}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Pairwise $\\auc$ for adjacent depth pairs with bootstrap 95\\% CIs and permutation $p$-values for boundary rows.\n$\\Kempirical = 2$ requires 1v2 $\\auc > \\theta{=}0.60$ and 2v3 $\\auc < \\theta$; CIs quantify boundary uncertainty.\nExtended results (all models) in Table~\\ref{tab:kstar_ci_extended}.}\n\\label{tab:kstar_ci}\n\\resizebox{\\textwidth}{!}{%\n\\begin{tabular}{lcccccccccc}\n\\toprule\n & \\multicolumn{2}{c}{Qwen-rw} & \\multicolumn{2}{c}{Pythia} & \\multicolumn{2}{c}{OLMo} & \\multicolumn{2}{c}{Qwen-cont} & \\multicolumn{2}{c}{Qwen-7B\\rlap{$^\\ddagger$}} \\\\\n\\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\\cmidrule(lr){6-7}\\cmidrule(lr){8-9}\\cmidrule(lr){10-11}\n & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI \\\\\n\\midrule\n0v1 & .9956 & & .9722 & & .9860 & & .9971 & & .9638 & [.961,\\,.967] \\\\\n1v2 & .6955 & [.686,\\,.704]\\rlap{$^*$} & .6074 & [.598,\\,.617]\\rlap{$^*$} & .5001 & [.496,\\,.519] & .6112 & [.602,\\,.621]\\rlap{$^*$} & .6168 & [.608,\\,.626]\\rlap{$^*$} \\\\\n2v3 & .5893 & [.580,\\,.599] & .5440 & [.534,\\,.554] & .4973 & [.486,\\,.509] & .5609 & [.551,\\,.571] & .5492 & [.539,\\,.559] \\\\\n3v4 & .5435 & & .5051 & & .5024\\rlap{$^\\S$} & & .5409 & & .5276 & \\\\\n4v5 & .5340 & & .5079 & & .4942 & & .5141 & & .5085 & \\\\\n\\bottomrule\n\\multicolumn{11}{l}{\\footnotesize $^*$Permutation $p < 0.001$ for all starred boundary comparisons ($\\auc > \\theta$).} \\\\\n\\multicolumn{11}{l}{\\footnotesize $^\\ddagger$Generator: Qwen2.5-7B (fp16); scorer: Qwen2.5-1.5B.} \\\\\n\\multicolumn{11}{l}{\\footnotesize $^\\S$OLMo 2v3 (0.497) $<$ 3v4 (0.502): non-monotonic reversal within noise ($\\Delta = 0.005$).} \\\\\n\\multicolumn{11}{l}{\\footnotesize Full results for all 10 configurations (including LLaMA-8B, Mistral-7B, Qwen-base, Gemma-2-2B, and Pythia-6.9B) in Table~\\ref{tab:kstar_ci_extended}.}\n\\end{tabular}}\n\\end{table*}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig2_auc_decay.pdf}\n\\caption{Pairwise $\\auc$ decay across adjacent depth pairs (0v1, 1v2, \\ldots, 4v5) for model-mode configurations (solid) and decoding strategies (dashed); shaded bands show bootstrap 95\\% confidence intervals. The horizontal dashed line marks $\\theta = 0.60$.}\n\\label{fig:auc_decay}\n\\end{figure}\n\nTable~\\ref{tab:kstar_ci} and Figure~\\ref{fig:auc_decay} show $\\Kempirical \\leq 2$ across all 10 configurations: 6/10 yield $\\Kempirical{=}2$ (Qwen$\\times$4, LLaMA-8B, Pythia-1.4B; 1v2 $\\auc$: 0.607--0.696; $p < 0.001$), while OLMo-1B, Mistral-7B, Pythia-6.9B, and Gemma-2-2B yield $\\Kempirical{=}1$ (1v2 $\\auc$: 0.500--0.598; Section~\\ref{sec:boundary_cases}).\nUnder Bonferroni correction (99.5\\% CIs), three of six $\\Kempirical{=}2$ configurations retain significance; the three marginal cases (Pythia-1.4B, Qwen-cont, LLaMA-8B; CI lower bounds 0.593--0.599) reflect narrow effect sizes rather than classification failure.\nBy architecture family: Qwen (4/4) and LLaMA (1/1) yield $\\Kempirical{\\geq}2$ at nominal significance; OLMo (1/1), Mistral (1/1), and Gemma (1/1) yield $\\Kempirical{=}1$; Pythia exhibits a scale-dependent split (1.4B: $\\Kempirical{=}2$, 6.9B: $\\Kempirical{=}1$).\nLLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9225$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).\nAll four decoding strategies likewise yield $\\Kempirical{=}2$ (Table~\\ref{tab:s2_decoding}).\nThe 1v2 spread due to generation mode ($\\Delta = 8.4$\\,pp within Qwen) exceeds the spread across $\\Kempirical{=}2$ continuation models ($\\Delta = 1.9$\\,pp).\n\n\\paragraph{Scale and instruction-tuning invariance.}\n$\\Kempirical{=}2$ persists from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$) both exceed $\\theta$, despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\\ $> 0.99$ at $\\leq$1.5B).\nA base-vs.-instruct ablation at 1.5B likewise yields $\\Kempirical = 2$ (1v2 $\\auc = 0.626$), confirming the boundary is not an instruction-tuning artifact.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.75\\textwidth]{figures/fig_kstar_theta.pdf}\n\\caption{$\\Kempirical(\\theta)$ sensitivity curve for five configurations. $\\Kempirical$: maximum discriminable depth; $\\theta$: AUC decision threshold. Four of five configurations yield $\\Kempirical{=}2$ at $\\theta{=}0.60$ (dashed line); OLMo yields $\\Kempirical{=}1$. At $\\theta{=}0.70$, all drop to $\\Kempirical{=}1$.}\n\\label{fig:kstar_theta}\n\\end{figure*}\n\nFigure~\\ref{fig:kstar_theta} displays the sensitivity surface across $\\theta \\in [0.55, 0.70]$: four of five configurations shown yield $\\Kempirical = 2$ within $\\theta \\in [0.51, 0.61]$ (OLMo: $\\Kempirical = 1$ throughout); at $\\theta{=}0.55$, two Qwen configurations reach $\\Kempirical = 3$; at $\\theta{=}0.70$, all drop to $\\Kempirical = 1$.\n\n%% ====================================================================\n\\subsection{Cross-Model Transfer}\n\\label{sec:transfer}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig3_transfer_heatmap.pdf}\n\\caption{Cross-model transfer heatmap (continuation-mode models). Each cell shows 6-class ordinal accuracy when trained on the row model and tested on the column model, divided by in-domain accuracy (retention rate). Pythia$\\leftrightarrow$OLMo: 90--92\\%.}\n\\label{fig:transfer_heatmap}\n\\end{figure}\n\nContinuation-mode classifiers transfer well across generators (Figure~\\ref{fig:transfer_heatmap}; full matrix in Table~\\ref{tab:s1_transfer}): Pythia$\\leftrightarrow$OLMo retains 90--92\\%, Qwen-cont$\\leftrightarrow$Pythia 84--85\\%, Qwen-cont$\\leftrightarrow$OLMo 80--85\\% (0v1 cross-model $\\auc > 0.96$ for all pairs).\nQwen-rewrite classifiers transfer poorly (61--63\\%), confirming reliance on mode-specific artifacts rather than generalizable depth features.\n\n\\paragraph{Cross-scorer validation.}\nReplacing the self-scorer with Pythia-1.4B or OLMo-1B preserves feature rankings ($\\rho > 0.90$) but attenuates absolute discriminability at the boundary (Table~\\ref{tab:crossscorer}).\nFeature ranking independence is a strong result: the same features dominate under all scorers.\n$\\Kempirical$ agreement, however, is signal-strength dependent: Qwen-rewrite (strong signal, 1v2 $\\auc = 0.696$) retains $\\Kempirical{=}2$ under all scorers, but Qwen-continuation (marginal, 1v2 $\\auc = 0.611$, only 0.011 above $\\theta$) drops to $\\Kempirical{=}1$ (Pythia: $0.5923$; OLMo: $0.5858$).\nA three-way ANOVA (Generator $\\times$ Scorer $\\times$ Depth-Pair; Table~\\ref{tab:anova_crossscorer}) confirms a statistically significant but modest Scorer main effect ($\\eta^2_p{=}.166$, $p < .001$) and a significant Generator$\\times$Scorer interaction ($\\eta^2_p{=}.146$), indicating that absolute AUC values are scorer-dependent even when $\\Kempirical$ classifications largely agree.\n\n%% ====================================================================\n\\subsection{Feature Ordering and Generation Mode}\n\\label{sec:feature_degradation}\n\\label{sec:generation_mode}\n\nAmong continuation-mode models, single-feature $\\auc$ rankings are highly correlated ($\\rho \\geq 0.85$; Table~\\ref{tab:top_features}).\nThe top-3 features (\\texttt{surp\\_d1\\_std}, \\texttt{surp\\_std}, \\texttt{surp\\_d2\\_std}) are shared across all three families, revealing that autoregressive generation progressively damps surprisal variability.\nQwen-rewrite diverges (\\texttt{freq\\_entropy} dominates), consistent with its poor cross-model transfer (61--63\\%).\nWithin Qwen, rewrite yields 1v2 $\\auc = 0.6955$ vs.\\ continuation's $0.6112$ ($\\Delta = +8.4$\\,pp); continuation mode is therefore recommended as the canonical condition.\n\n%% ====================================================================\n\\subsection{Neural Probe}\n\\label{sec:neural_probe}\n\nReplacing the 15D features with frozen encoder hidden states (MLP probe; Table~\\ref{tab:neural_probe_crossmodel}), Qwen achieves $\\Kempirical^{\\text{neural}} = 3$ (2v3 $\\auc = 0.6159$), while Pythia remains at $\\Kempirical^{\\text{neural}} = 2$ ($\\auc_{2v3} = 0.5963$); OLMo yields $\\Kempirical^{\\text{neural}} = 1$ (1v2 $\\auc = 0.5054$, consistent with its 15D boundary).\nWe hypothesize that the Qwen-only elevation reflects self-familiarity artifacts, consistent with the poor transfer observed in Section~\\ref{sec:transfer}; the 15D features yield $\\Kempirical = 2$ for most families (OLMo: $\\Kempirical = 1$).\n\n\\noindent\\begin{minipage}{\\columnwidth}\n\\centering\n\\footnotesize\n\\captionof{table}{Neural probe pairwise AUC using frozen-encoder MLP. Each cell reports AUC for classifying depth $d$ vs.\\ $d{+}1$ text. $\\Kempirical^{\\text{neural}}$: maximum depth where AUC exceeds $\\theta = 0.60$.}\n\\label{tab:neural_probe_crossmodel}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Model} & \\textbf{2v3 $\\auc$} & \\textbf{95\\% CI} & $\\Kempirical^{\\text{neural}}$ \\\\\n\\midrule\nQwen-1.5B  & 0.6159 & $[0.610,\\,0.622]$ & 3 \\\\\nPythia-1.4B & 0.5963 & $[0.589,\\,0.603]$ & 2 \\\\\nOLMo-1B    & 0.5056 & $[0.497,\\,0.516]$ & 1\\rlap{$^\\dagger$} \\\\\n\\bottomrule\n\\multicolumn{4}{l}{\\footnotesize $^\\dagger$OLMo 1v2 $\\auc = 0.5054$ (below $\\theta$); $\\Kempirical^{\\text{neural}} = 1$.}\n\\end{tabular}}\n\\end{minipage}\n\n%% ====================================================================\n\\subsection{Cross-Domain Variation}\n\\label{sec:cross_domain}\n\nThe preceding experiments use C4 (general web text).\nTo test domain dependence, we evaluate on Wikipedia ($n{=}5{,}000$) and arXiv abstracts ($n{=}2{,}200$) across three architecture families.\nWikipedia yields $\\Kempirical{=}2$ (1v2 $\\auc = 0.619$, 2v3 $\\auc = 0.550$; Table~\\ref{tab:domain_kstar}), matching the C4 baseline.\nQwen-1.5B, Pythia-1.4B, and LLaMA-3.1-8B yield $\\Kempirical{=}3$ for arXiv (Table~\\ref{tab:domain_kstar}): 2v3 $\\auc = 0.644\\;[0.628,\\,0.658]$, $0.655\\;[0.640,\\,0.669]$, and $0.620\\;[0.605,\\,0.635]$ respectively (bootstrap CI lower bounds above $\\theta$; permutation $p < 0.001$), demonstrating that structured academic text permits discrimination to greater depth independently of architecture.\nThe elevated signal reflects higher per-generation distributional shift (1v2 JSD $= 0.077$ vs.\\ ${\\sim}0.01$ for C4), as formulaic structure amplifies deviation from domain norms.\nWe additionally evaluate on CodeSearchNet Python ($n{=}5{,}000$, continuation mode); all four tested models (Qwen-1.5B, Qwen-7B, LLaMA-8B, Mistral-7B) yield $\\Kempirical{=}2$ (Table~\\ref{tab:domain_kstar}), matching the C4 baseline.\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\caption{Cross-domain $\\Kempirical$ comparison. $\\Kempirical{=}2$ for C4, Wikipedia, and Code; $\\Kempirical{=}3$ for arXiv (three families confirmed in text; representative rows shown).}\n\\label{tab:domain_kstar}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Model} & \\textbf{1v2 $\\auc$} & \\textbf{2v3 $\\auc$} & $\\Kempirical$ \\\\\n\\midrule\narXiv & Qwen-1.5B\\rlap{$^\\dagger$}  & .858 & .644 & 3 \\\\\narXiv & Pythia-1.4B & .805 & .655 & 3 \\\\\nC4    & Qwen-1.5B\\rlap{$^\\dagger$}  & .626 & .550 & 2 \\\\\nWiki  & Qwen-1.5B\\rlap{$^\\dagger$}  & .619 & .550 & 2 \\\\\nCode  & Qwen-1.5B\\rlap{$^\\dagger$}  & .738 & .530 & 2 \\\\\nCode  & LLaMA-8B   & .739 & .510 & 2 \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize $^\\dagger$Qwen2.5-1.5B (base, continuation mode).}\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Robustness.}\n\\label{sec:robustness}\n$\\Kempirical{=}2$ holds across segment lengths of 128, 256, and 512 tokens (Table~\\ref{tab:s11_length_ablation}); at 512 tokens the 1v2 CI lower bound falls marginally below $\\theta$ but 2v3 remains well below $\\theta$ at all lengths ($\\leq 0.572$).\nSeed robustness testing (seed $= 123$ vs.\\ primary $= 42$; Table~\\ref{tab:seed_robustness}) confirms $\\Kempirical$ stability in 2/3 configurations; the one marginal shift (Qwen-Wikipedia $\\Kempirical{=}2 \\to 3$, 2v3 $\\auc = 0.607$) has one of five folds below $\\theta$.\nThe ${\\pm}9$\\,pp absolute AUC variation across seeds strengthens the case for threshold-based $\\Kempirical$ over raw AUC comparisons.\n\n%% ====================================================================\n\\subsection{Binary Detector Confidence}\n\\label{sec:binary_confidence}\n\nBinary detectors (DivEye~\\cite{basani2026diveye}, Binoculars~\\cite{hans2024binoculars}) remain effective for human-vs.-machine classification but provide no usable depth signal beyond this binary boundary.\nPairwise $\\auc$ yields $\\Kempirical^{\\text{binary}} \\leq 1$; moderate rank correlations with depth ($|\\rho| = 0.06$--$0.46$; Table~\\ref{tab:s9_binary_spearman}) are driven entirely by the 0v1 gap rather than fine-grained depth discrimination, and multiple conditions exhibit non-monotonic AUC at deeper pairs.\n",
      "numLines": 165,
      "startLine": 1,
      "totalLines": 165
    }
  },
  "sourceToolAssistantUUID": "53e0e500-a8f7-49f4-9f15-6c2e29e59627",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-23T11:01:50.163Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KLYweg96e422SAmQZQrNsc`</summary>

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
  "parentUuid": "8c67ad03-ec6a-417c-9adb-8e135e916145",
  "isSidechain": false,
  "requestId": "req_011CbKPP5Pf1zgmH6Q6m6bZ1",
  "type": "assistant",
  "uuid": "098b3915-dcf1-4a54-a305-684300636885",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RH1Vc9duTAip2PnkbYXraS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 464,
      "cache_read_input_tokens": 24153,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 350,
          "cache_read_input_tokens": 24153,
          "cache_creation_input_tokens": 464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 464
          },
          "type": "message"
        }
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

_source line 18 · 2026-05-23T11:01:50.168Z_

<details><summary>↩ Tool result · `toolu_01KLYweg96e422SAmQZQrNsc`</summary>

```text
1	\appendix
2	\section{Supplementary Materials}
3	\label{sec:appendix}
4	
5	This appendix provides supplementary figures, detailed experimental tables, dataset statistics, and complete feature descriptions referenced in the main text.
6	
7	\begin{figure}[t]
8	\centering
9	\includegraphics[width=\columnwidth]{figures/fig_filtering_strategies.pdf}
10	\caption{Downstream performance of all filtering strategies (5 seeds, $\pm$1 std). Binary-ours (green) minimizes MMLU degradation; graduated $\alpha$ sweep shows monotonic convergence toward binary. Dashed line: base model (no fine-tuning).}
11	\label{fig:filtering_strategies}
12	\end{figure}
13	
14	\paragraph{Feature ranking and cross-model consistency.}
15	Table~\ref{tab:top_features} reports per-model single-feature AUC rankings.
16	Surprisal derivative features (\texttt{surp\_d1\_std}, \texttt{surp\_d2\_std}) consistently rank among the top three across all continuation-mode models (Pythia, OLMo, Qwen-cont), with pairwise Spearman $\rho \geq 0.85$.
17	The rewrite-mode model (Qwen-rw) diverges by placing \texttt{freq\_entropy} first, reflecting a distributional shift that is lexical rather than surprisal-driven.
18	This scorer-invariant ranking supports the use of a fixed 15-dimensional feature set across generators without per-model feature selection.
19	
20	%%% Feature ranking table (moved from main text)
21	\begin{table}[!htbp]
22	\centering
23	\small
24	\caption{Top-3 features by single-feature $\auc$ ranking. Bold: shared across all continuation-mode models. Spearman $\rho$ (continuation pairs): Pythia--OLMo 0.95, Pythia--Qwen-cont 0.91, OLMo--Qwen-cont 0.85.}
25	\label{tab:top_features}
26	\resizebox{\columnwidth}{!}{%
27	\begin{tabular}{cllll}
28	\toprule
29	Rank & Pythia & OLMo & Qwen-rw & Qwen-cont \\
30	\midrule
31	1 & \textbf{\texttt{surp\_d1\_std}} & \textbf{\texttt{surp\_std}} & \texttt{freq\_entropy} & \textbf{\texttt{surp\_d1\_std}} \\
32	2 & \textbf{\texttt{surp\_d2\_std}} & \textbf{\texttt{surp\_d1\_std}} & \textbf{\texttt{surp\_std}} & \textbf{\texttt{surp\_std}} \\
33	3 & \textbf{\texttt{surp\_std}} & \textbf{\texttt{surp\_d2\_std}} & \textbf{\texttt{surp\_d1\_std}} & \textbf{\texttt{surp\_d2\_std}} \\
34	\bottomrule
35	\end{tabular}
36	}
37	\end{table}
38	
39	Table~\ref{tab:s1_transfer} reports the cross-model transfer accuracy matrix.
40	Classifiers trained on continuation-mode generators (Pythia, OLMo, Qwen-cont) transfer well to each other, with off-diagonal accuracy retaining 80--92\% of in-distribution performance.
41	The asymmetry between rewrite-mode and continuation-mode transfer (61--63\%) confirms that generation mode, rather than model family, is the primary axis of distributional variation (Section~\ref{sec:discussion}).
42	
43	%%% Table S1: Cross-Transfer Confusion Matrix (exp-013)
44	\begin{table}[!htbp]
45	  \centering
46	  \small
47	  \caption{Cross-model transfer accuracy matrix. Diagonal (\textbf{bold}): within-model; off-diagonal: cross-model. Retention: Pythia$\leftrightarrow$OLMo 91--92\%, Qwen-cont$\leftrightarrow$Pythia 83--85\%, Qwen-rw$\to$others 61--63\%.}
48	  \label{tab:s1_transfer}
49	  \resizebox{\columnwidth}{!}{%
50	  \begin{tabular}{lcccc}
51	    \toprule
52	    \textbf{Train} & Qwen-rw & Pythia & OLMo & Qwen-cont \\
53	    \midrule
54	    Qwen-rw   & \textbf{.423} & .259 & .265 & .347 \\
55	    Pythia    & .272 & \textbf{.386} & .353 & .329 \\
56	    OLMo      & .277 & .345 & \textbf{.382} & .324 \\
57	    Qwen-cont & .344 & .328 & .311 & \textbf{.388} \\
58	    \bottomrule
59	  \end{tabular}}
60	\end{table}
61	
62	\paragraph{Dataset construction.}
63	Table~\ref{tab:s4_dataset_stats} summarizes the generational depth corpus.
64	Each depth level contains 5{,}000 passages, yielding 30{,}000 total samples across six depths (0--5).
65	Depth~0 consists of human-written seed texts from the C4 English validation split, truncated to 256 subword tokens.
66	Subsequent depths are generated recursively: each depth-$k$ passage is produced by prompting the generator with the corresponding depth-$(k{-}1)$ passage.
67	The four model-mode configurations (Qwen-rw, Pythia-cont, OLMo-cont, Qwen-cont) share identical depth-0 seeds and generation pipeline, differing only in generator identity and prompting strategy (rewrite vs.\ continuation).
68	
69	%%% Table S4: Dataset Statistics
70	\begin{table}[!htbp]
71	  \centering
72	  \small
73	  \caption{Dataset statistics for the generational depth corpus. Depth~0 contains human-written seed texts sampled from the C4 English validation split and truncated to 256 subword tokens. Depths~1--5 are recursively generated by Qwen2.5-1.5B-Instruct (nucleus sampling, $p{=}0.95$, $T{=}1.0$). Token counts use whitespace tokenization. Statistics shown for the primary Qwen-rewrite corpus; the other three model-mode configurations (Pythia-cont, OLMo-cont, Qwen-cont) share the same generation pipeline and corpus structure.}
74	  \label{tab:s4_dataset_stats}
75	  \resizebox{\columnwidth}{!}{%
76	  \begin{tabular}{clrl}
77	    \toprule
78	    \textbf{Depth} & \textbf{$N$ samples} & \textbf{Mean tokens} & \textbf{Source} \\
79	    \midrule
80	    0 & 5{,}000 & 147.8 & C4 validation (human) \\
81	    1 & 5{,}000 & 207.1 & Qwen2.5-1.5B rewrite \\
82	    2 & 5{,}000 & 206.1 & Qwen2.5-1.5B rewrite \\
83	    3 & 5{,}000 & 208.0 & Qwen2.5-1.5B rewrite \\
84	    4 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\
85	    5 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\
86	    \midrule
87	    \multicolumn{2}{l}{Total} & \multicolumn{2}{l}{30{,}000 samples} \\
88	    \bottomrule
89	  \end{tabular}}
90	\end{table}
91	
92	%%% Table S2: Decoding Ablation AUC (exp-003)
93	\begin{table*}[t]
94	  \centering
95	  \caption{Pairwise AUC with bootstrap 95\% CIs across depth pairs for four decoding configurations (all using Qwen2.5-1.5B-Instruct in rewrite mode; 10{,}000 bootstrap resamples). The horizontal rule between depth pairs 1\,vs.\,2 and 2\,vs.\,3 marks the empirical detectability boundary $\Kempirical=2$. Bottom rows report cross-configuration Spearman $\rho$ on per-feature discriminative-power rankings.}
96	  \label{tab:s2_decoding}
97	  \footnotesize
98	  \begin{tabular}{lcccc}
99	    \toprule
100	    \textbf{Depth Pair} & \textbf{Greedy} & \textbf{Nuc $p{=}0.9$, $T{=}1.0$} & \textbf{Nuc $p{=}0.95$, $T{=}0.7$} & \textbf{Nuc $p{=}0.95$, $T{=}1.2$} \\
101	    \midrule
102	    0 vs.\ 1 & $.980\;[.977,\,.982]$ & $.995\;[.993,\,.996]$ & $.988\;[.986,\,.990]$ & $.998\;[.998,\,.999]$ \\
103	    1 vs.\ 2 & $.689\;[.680,\,.698]$ & $.687\;[.677,\,.695]$ & $.689\;[.680,\,.697]$ & $.704\;[.695,\,.713]$ \\
104	    \cmidrule(lr){1-5}
105	    2 vs.\ 3 & $.561\;[.552,\,.571]$ & $.592\;[.582,\,.601]$\rlap{$^\dagger$} & $.590\;[.581,\,.600]$ & $.582\;[.572,\,.592]$ \\
106	    3 vs.\ 4 & $.540\;[.531,\,.550]$ & $.547\;[.537,\,.557]$ & $.539\;[.529,\,.549]$ & $.529\;[.519,\,.540]$ \\
107	    4 vs.\ 5 & $.514\;[.503,\,.524]$ & $.507\;[.496,\,.517]^{\ddagger}$ & $.535\;[.524,\,.545]$ & $.524\;[.513,\,.535]$ \\
108	    \midrule
109	    \multicolumn{5}{l}{\textbf{Cross-config feature Spearman $\rho$}} \\
110	    \midrule
111	    \multicolumn{2}{l}{Greedy vs.\ Nuc $p{=}0.9$} & 0.600 &
112	    \multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\ $T{=}0.7$} & 0.782 \\
113	    \multicolumn{2}{l}{Greedy vs.\ $T{=}0.7$} & 0.914 &
114	    \multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\ $T{=}1.2$} & 0.893 \\
115	    \multicolumn{2}{l}{Greedy vs.\ $T{=}1.2$} & 0.532 &
116	    \multicolumn{1}{l}{$T{=}0.7$ vs.\ $T{=}1.2$} & 0.668 \\
117	    \bottomrule
118	    \multicolumn{5}{l}{${}^{\dagger}$\,CI upper bound (0.601) marginally exceeds $\theta{=}0.60$ by 0.001.} \\
119	    \multicolumn{5}{l}{${}^{\ddagger}$\,Permutation $p = 0.12$ (not significant). All other pairs $p < 0.01$.}
120	  \end{tabular}
121	\end{table*}
122	
123	%%% Table S2b: Extended K* CI (all models including new additions)
124	\begin{table*}[t]
125	  \centering
126	  \scriptsize
127	  \caption{Extended pairwise $\auc$ with bootstrap 95\% CIs for all model configurations including new additions.
128	  This table extends Table~\ref{tab:kstar_ci} in the main text with Qwen-base, LLaMA-8B, Mistral-7B, Pythia-6.9B (nucleus), and Gemma-2-2B configurations.
129	  $\Kempirical = 2$ holds for 6/10 conditions at $\theta{=}0.60$ (OLMo-1B, Mistral-7B, Pythia-6.9B, Gemma-2-2B: $\Kempirical{=}1$).}
130	  \label{tab:kstar_ci_extended}
131	  \resizebox{\textwidth}{!}{%
132	  \begin{tabular}{lcccccccccccccccccccc}
133	    \toprule
134	     & \multicolumn{2}{c}{Qwen-rw} & \multicolumn{2}{c}{Pythia} & \multicolumn{2}{c}{OLMo} & \multicolumn{2}{c}{Qwen-cont} & \multicolumn{2}{c}{Qwen-7B\rlap{$^\ddagger$}} & \multicolumn{2}{c}{Qwen-base} & \multicolumn{2}{c}{LLaMA-8B} & \multicolumn{2}{c}{Mistral-7B} & \multicolumn{2}{c}{Pythia-6.9B\rlap{$^\S$}} & \multicolumn{2}{c}{Gemma-2B} \\
135	    \cmidrule(lr){2-3}\cmidrule(lr){4-5}\cmidrule(lr){6-7}\cmidrule(lr){8-9}\cmidrule(lr){10-11}\cmidrule(lr){12-13}\cmidrule(lr){14-15}\cmidrule(lr){16-17}\cmidrule(lr){18-19}\cmidrule(lr){20-21}
136	     & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI & $\auc$ & 95\% CI \\
137	    \midrule
138	    0v1 & .9956 & & .9722 & & .9860 & & .9971 & & .9638 & [.961,\,.967] & .987 & [.985,\,.989] & .9224 & [.917,\,.927] & .9170 & & .9599 & & .953 & [.949,\,.957] \\
139	    1v2 & .6955 & [.686,\,.704]\rlap{$^*$} & .6074 & [.598,\,.617]\rlap{$^*$} & .5001 & [.496,\,.519] & .6112 & [.602,\,.621]\rlap{$^*$} & .6168 & [.608,\,.626]\rlap{$^*$} & .626 & [.617,\,.635]\rlap{$^*$} & .6123 & [.603,\,.622]\rlap{$^*$} & .5750 & & .5955 & & .5981 & [.588,\,.608] \\
140	    2v3 & .5893 & [.580,\,.599] & .5440 & [.534,\,.554] & .4973 & [.486,\,.509] & .5609 & [.551,\,.571] & .5492 & [.539,\,.559] & .550 & [.540,\,.560] & .5273 & [.517,\,.538] & .5369 & & .5298 & & .534 & [.523,\,.545] \\
141	    3v4 & .5435 & & .5051 & & .5024 & & .5409 & & .5276 & & .529 & [.519,\,.540] & .5168 & [.506,\,.528] & .5174 & & .5135 & & .5033 & [.492,\,.514] \\
142	    4v5 & .5340 & & .5079 & & .4942 & & .5141 & & .5085 & & .518 & [.508,\,.529] & .5159 & [.505,\,.527] & .5175 & & ---\rlap{$^\|$} & & .5025 & [.492,\,.514] \\
143	    \bottomrule
144	    \multicolumn{21}{l}{\footnotesize $^*$Permutation $p < 0.001$ for all boundary comparisons.} \\
145	    \multicolumn{21}{l}{\footnotesize $^\ddagger$Generator: Qwen2.5-7B (fp16); scorer: Qwen2.5-1.5B.} \\
146	    \multicolumn{21}{l}{\footnotesize $^\|$$\Kempirical{=}1$; 4v5 not required for boundary determination.} \\
147	    \multicolumn{21}{l}{\footnotesize $^\S$Pythia-6.9B evaluated separately; nucleus sampling ($p{=}0.95$, $T{=}1.0$), same as all other models.}
148	  \end{tabular}}% end resizebox
149	\end{table*}
150	
151	%%% Table S3: LLM Zero-Shot Confusion Matrices (exp-011)
152	\begin{table}[t]
153	  \centering
154	  \scriptsize
155	  \caption{LLM zero-shot depth classification: $5{\times}5$ confusion matrices (Exp-011). Both frontier LLMs achieve high binary detection accuracy (GPT-5.5: 0.878; Claude Opus~4.6: 0.882) but near-chance 5-class accuracy (${\sim}$0.33 vs.\ OBD-LightGBM 0.386). Per-depth recall in Table~\ref{tab:s3c_perdepth}.}
156	  \label{tab:s3_llm_zeroshot}
157	
158	  \vspace{0.3em}
159	  \textbf{(a)} GPT-5.5 ($N{=}500$, acc${=}0.332$, MAE${=}1.102$)
160	  \vspace{1pt}
161	
162	  \begin{tabular}{lcccccc}
163	    \toprule
164	    & \multicolumn{5}{c}{Predicted Depth} & \\
165	    \cmidrule(lr){2-6}
166	    True & 0 & 1 & 2 & 3 & 4 & Rec. \\
167	    \midrule
168	    0 & \textbf{77} & 18 &  4 &  0 &  1 & .770 \\
169	    1 &  9 & \textbf{19} & 36 & 24 & 12 & .190 \\
170	    2 &  8 & 10 & \textbf{38} & 35 &  9 & .380 \\
171	    3 & 10 & 16 & 35 & \textbf{24} & 15 & .240 \\
172	    4 & 11 & 13 & 50 & 18 &  \textbf{8} & .080 \\
173	    \bottomrule
174	  \end{tabular}
175	
176	  \vspace{4pt}
177	  \textbf{(b)} Claude Opus~4.6 ($N{=}499$, acc${=}0.331$, MAE${=}1.150$)
178	  \vspace{1pt}
179	
180	  \begin{tabular}{lcccccc}
181	    \toprule
182	    & \multicolumn{5}{c}{Predicted Depth} & \\
183	    \cmidrule(lr){2-6}
184	    True & 0 & 1 & 2 & 3 & 4 & Rec. \\
185	    \midrule
186	    0 & \textbf{69} & 26 &  3 &  0 &  2 & .690 \\
187	    1 &  8 & \textbf{21} & 32 & 11 & 28 & .210 \\
188	    2 &  6 & 36 & \textbf{28} &  5 & 25 & .280 \\
189	    3 &  7 & 20 & 31 & \textbf{10} & 31 & .100 \\
190	    4 &  7 & 28 & 22 &  6 & \textbf{37} & .370 \\
191	    \bottomrule
192	  \end{tabular}
193	\end{table}
194	
195	\begin{table}[t]
196	  \centering
197	  \small
198	  \caption{Per-depth recall (\%) on balanced $N{=}500$ test set. OBD's nominal overall accuracy gap originates from depth-0; all methods fail at depths $\geq 2$, consistent with $\Kempirical = 2$.}
199	  \label{tab:s3c_perdepth}
200	  \resizebox{\columnwidth}{!}{%
201	  \begin{tabular}{lccccc}
202	    \toprule
203	    & Depth 0 & Depth 1 & Depth 2 & Depth 3 & Depth 4 \\
204	    \midrule
205	    OBD-LightGBM & \textbf{96} & \textbf{39} & 14 & 19 & 22 \\
206	    GPT-5.5      & 77 & 19 & \textbf{38} & \textbf{24} &  8 \\
207	    Claude Opus~4.6 & 69 & 21 & 28 & 10 & \textbf{37} \\
208	    \bottomrule
209	  \end{tabular}}
210	\end{table}
211	
212	%%% Table: Token Length and EOS Truncation Analysis
213	\begin{table}[t]
214	  \centering
215	  \scriptsize
216	  \caption{Mean subword token count per depth and EOS truncation rate (\%) for depth~1+ across all model configurations (generation limit: 256 tokens). Depth~0 (human text) is shared across configurations. Depths 1--5 show no systematic length trend; the 0v1 length asymmetry (human texts shorter) makes detection \emph{more conservative}, not inflated. See Section~\ref{sec:length_confound}.}
217	  \label{tab:token_length}
218	  \resizebox{\columnwidth}{!}{%
219	  \begin{tabular}{lcccccccc}
220	    \toprule
221	    & \multicolumn{6}{c}{\textbf{Mean Token Count}} & & \\
222	    \cmidrule(lr){2-7}
223	    \textbf{Model} & D0 & D1 & D2 & D3 & D4 & D5 & \textbf{EOS\%} & \textbf{Sev.} \\
224	    \midrule
225	    Qwen-rw (1.5B)  & 191 & 254 & 252 & 254 & 254 & 254 & 7--11 & Mild \\
226	    Pythia-1.4B      & 192 & 214 & 215 & 216 & 217 & 218 & 34--36 & High \\
227	    OLMo-1B          & 192 & 256 & 256 & 256 & 256 & 256 & $<$1 & Negl. \\
228	    Qwen-cont (1.5B) & 191 & 244 & 238 & 240 & 240 & 238 & 17--20 & Mod. \\
229	    Qwen-7B          & 191 & 196 & 195 & 193 & 197 & 197 & 45--47 & High \\
230	    \midrule
231	    \multicolumn{9}{l}{\textit{Decoding ablation (Qwen-rw 1.5B)}} \\
232	    \quad Greedy          & 191 & 253 & 252 & 253 & 254 & 254 & 8--12 & Mild \\
233	    \quad Nuc $p{=}0.9$   & 191 & 254 & 251 & 254 & 253 & 254 & 8--16 & Mild \\
234	    \quad $T{=}0.7$       & 191 & 253 & 251 & 253 & 253 & 254 & 8--14 & Mild \\
235	    \quad $T{=}1.2$       & 191 & 254 & 252 & 253 & 254 & 254 & 8--16 & Mild \\
236	    \bottomrule
237	    \multicolumn{9}{l}{EOS\%: generation terminated via EOS before 256-token limit. Ranges span depths 1--5.}
238	  \end{tabular}}
239	\end{table}
240	
241	%%% Table S5: Complete 15-D Feature Descriptions
242	\begin{table*}[t]
243	  \centering
244	  \caption{Complete description of the 15-dimensional feature set used by the OBD classifier. Features are grouped into three families: surprisal statistics (9~dims) computed from Qwen2.5-1.5B token-level log-probabilities, lexical diversity (3~dims), and frequency tail shape (3~dims). All features are computed per document.}
245	  \label{tab:s5_features}
246	  \begin{tabular}{llp{0.45\textwidth}l}
247	    \toprule
248	    \textbf{Group} & \textbf{Feature} & \textbf{Description} & \textbf{Range} \\
249	    \midrule
250	    \multirow{9}{*}{\rotatebox[origin=c]{90}{\textsc{Surprisal}}}
251	    & \texttt{surp\_mean}   & Mean token surprisal $\frac{1}{T}\sum_t -\log p(x_t \mid x_{&lt;t})$ & $\mathbb{R}^+$ \\
252	    & \texttt{surp\_std}    & Standard deviation of token surprisal & $\mathbb{R}^+$ \\
253	    & \texttt{surp\_skew}   & Skewness of the surprisal distribution & $\mathbb{R}$ \\
254	    & \texttt{surp\_kurt}   & Excess kurtosis of the surprisal distribution & $\mathbb{R}$ \\
255	    & \texttt{surp\_d1\_mean} & Mean of first-order surprisal differences $\Delta s_t = s_{t+1} - s_t$ & $\mathbb{R}$ \\
256	    & \texttt{surp\_d1\_std}  & Std of first-order surprisal differences & $\mathbb{R}^+$ \\
257	    & \texttt{surp\_d1\_skew} & Skewness of first-order surprisal differences & $\mathbb{R}$ \\
258	    & \texttt{surp\_d2\_mean} & Mean of second-order differences $\Delta^2 s_t$ & $\mathbb{R}$ \\
259	    & \texttt{surp\_d2\_std}  & Std of second-order surprisal differences & $\mathbb{R}^+$ \\
260	    \midrule
261	    \multirow{3}{*}{\rotatebox[origin=c]{90}{\textsc{Lex}}}
262	    & \texttt{ttr}          & Type-token ratio: $|V| / T$ & $[0, 1]$ \\
263	    & \texttt{hapax\_ratio} & Hapax legomena ratio: freq-1 types / unique types & $[0, 1]$ \\
264	    & \texttt{self\_bleu}   & Mean 4-gram BLEU against 100 random same-depth samples & $[0, 1]$ \\
265	    \midrule
266	    \multirow{3}{*}{\rotatebox[origin=c]{90}{\textsc{Freq}}}
267	    & \texttt{freq\_kurtosis}  & Excess kurtosis of word frequency distribution & $\mathbb{R}$ \\
268	    & \texttt{freq\_entropy}   & Shannon entropy of word frequencies: $-\sum p_w \log_2 p_w$ & $\mathbb{R}^+$ \\
269	    & \texttt{low\_freq\_ratio} & Proportion of vocabulary with count $\leq 2$ & $[0, 1]$ \\
270	    \bottomrule
271	  \end{tabular}
272	\end{table*}
273	
274	%%% Tables S6 & S7: Side by side in a single table* to avoid table*/table overlap
275	\begin{table*}[t]
276	\begin{minipage}[t]{0.45\textwidth}
277	  \centering
278	  \small
279	  \captionof{table}{LightGBM hyperparameters for the pairwise OBD (Ordinal Binary Decomposition) classifier used throughout the paper. One binary classifier is trained per adjacent depth pair $(k, k{+}1)$; 5-fold GroupKFold cross-validation is grouped by \texttt{doc\_id} to prevent data leakage from the same seed document appearing in both train and test.}
280	  \label{tab:s6_lgbm_params}
281	  \begin{tabular}{ll}
282	    \toprule
283	    \textbf{Parameter} & \textbf{Value} \\
284	    \midrule
285	    \texttt{n\_estimators}      & 200 \\
286	    \texttt{learning\_rate}     & 0.05 \\
287	    \texttt{max\_depth}         & 6 \\
288	    \texttt{num\_leaves}        & 31 \\
289	    \texttt{verbose}            & $-1$ \\
290	    \texttt{n\_jobs}            & $-1$ (all cores) \\
291	    Cross-validation            & 5-fold GroupKFold \\
292	    Grouping key                & \texttt{doc\_id} \\
293	    Objective                   & Binary (per depth pair) \\
294	    \bottomrule
295	  \end{tabular}
296	\end{minipage}\hfill
297	\begin{minipage}[t]{0.52\textwidth}
298	  \centering
299	  \small
300	  \captionof{table}{Neural probe architecture and training details (Exp-015). Applied to all three model families (Qwen2.5-1.5B, Pythia-1.4B, OLMo-1B): each model's frozen hidden states are average-pooled into document embeddings and classified by a two-hidden-layer MLP.}
301	  \label{tab:s7_neural_probe}
302	  \resizebox{\textwidth}{!}{%
303	  \begin{tabular}{ll}
304	    \toprule
305	    \textbf{Component} & \textbf{Details} \\
306	    \midrule
307	    \multicolumn{2}{l}{\textit{Embedding extraction}} \\
308	    Base models       & Qwen2.5-1.5B / Pythia-1.4B / OLMo-1B (frozen) \\
309	    Representation    & Last hidden state, attention-masked avg pool \\
310	    Embedding dim     & 1536 / 2048 / 2048 \\
311	    Max sequence len   & 512 tokens \\
312	    \midrule
313	    \multicolumn{2}{l}{\textit{MLP classifier}} \\
314	    Architecture      & $d_{\text{emb}} \to 512 \to 256 \to 6$ \\
315	    Activations       & ReLU \\
316	    Dropout           & 0.1 (after each hidden layer) \\
317	    Output            & 6-class softmax \\
318	    \midrule
319	    \multicolumn{2}{l}{\textit{Training}} \\
320	    Optimizer         & Adam ($\text{lr} = 10^{-3}$, weight decay $= 10^{-4}$) \\
321	    Loss              & Cross-entropy \\
322	    Batch size        & 256 \\
323	    Max epochs        & 20 \\
324	    Early stopping    & Patience = 5 (validation loss) \\
325	    Cross-validation  & 5-fold GroupKFold \\
326	    \bottomrule
327	  \end{tabular}%
328	  }
329	\end{minipage}
330	\end{table*}
331	
332	%%% Table S8: Per-Model Bootstrap CI Results (exp-007)
333	\begin{table}[t]
334	  \centering
335	  \scriptsize
336	  \caption{Pairwise AUC with bootstrap 95\% CIs for four model-mode configurations (1{,}000 resamples). All boundary pairs ($\auc > \theta$) $p < 0.01$; OLMo 1v2--4v5 non-significant ($p > 0.09$).}
337	  \label{tab:s8_cv_folds}
338	  \resizebox{\columnwidth}{!}{%
339	  \begin{tabular}{lcccc}
340	    \toprule
341	    & \textbf{Qwen-rw} & \textbf{Pythia} & \textbf{OLMo} & \textbf{Qwen-cont} \\
342	    \midrule
343	    0v1 & $.996\;[.995,.997]$ & $.993\;[.992,.994]$ & $.986\;[.984,.988]$ & $.997\;[.996,.998]$ \\
344	    1v2 & $.696\;[.686,.704]$ & $.607\;[.598,.617]$ & $.500\;[.496,.519]$ & $.611\;[.602,.621]$ \\
345	    \cmidrule(lr){1-5}
346	    2v3 & $.589\;[.580,.599]$ & $.551\;[.542,.563]$ & $.497\;[.486,.509]$ & $.561\;[.551,.571]$ \\
347	    3v4 & $.544\;[.533,.555]$ & $.515\;[.504,.526]$ & $.502\;[.491,.513]$ & $.541\;[.531,.551]$ \\
348	    4v5 & $.534\;[.524,.545]$ & $.514\;[.502,.525]$ & $.494\;[.483,.506]$ & $.514\;[.504,.526]$ \\
349	    \bottomrule
350	  \end{tabular}}
351	\end{table}
352	
353	%%% Table S9: Binary Detector Spearman ρ (exp-012)
354	\begin{table}[t]
355	  \centering
356	  \scriptsize
357	  \caption{Spearman $\rho$ between binary detector scores and true depth, and 6-class accuracy. Correlations driven by 0v1; scores do not track depth beyond generation~1. Qwen-rw exhibits reversed sign ($\rho > 0$).}
358	  \label{tab:s9_binary_spearman}
359	  \resizebox{\columnwidth}{!}{%
360	  \begin{tabular}{lcccc}
361	    \toprule
362	    & \textbf{Qwen-rw} & \textbf{Pythia} & \textbf{OLMo} & \textbf{Qwen-cont} \\
363	    \midrule
364	    \multicolumn{5}{l}{\textit{Spearman $\rho$}} \\
365	    \quad log-PPL (ref)      & $-0.123$ & $-0.297$ & $-0.378$ & $-0.389$ \\
366	    \quad log-PPL (obs.)     & $+0.082$ & $-0.453$ & $-0.461$ & $-0.162$ \\
367	    \quad PPL ratio           & $+0.119$ & $-0.392$ & $-0.407$ & $-0.058$ \\
368	    \midrule
369	    6-class acc.              & 0.199    & 0.130    & 0.127    & 0.183 \\
370	    \bottomrule
371	    \multicolumn{5}{l}{Random baseline: 0.167} \\
372	  \end{tabular}}
373	\end{table}
374	
375	%%% Table S10: Pythia Decoding Ablation (exp-020)
376	\begin{table}[t]
377	  \centering
378	  \scriptsize
379	  \caption{Pythia-1.4B pairwise $\auc$ under four decoding configs (10K bootstrap). $^\dagger$Greedy triggers repetition collapse (4-gram repeat: $d_0{=}0.01 \to d_1{=}0.72$).}
380	  \label{tab:s10_pythia_decoding}
381	  \resizebox{\columnwidth}{!}{%
382	  \begin{tabular}{lcccc}
383	    \toprule
384	    & \textbf{Greedy}$^\dagger$ & \textbf{$p{=}0.9$} & \textbf{$T{=}0.7$} & \textbf{$T{=}1.2$} \\
385	    \midrule
386	    0v1 & $.999$ & $.995$ & $.996$ & $.994$ \\
387	    1v2 & $.884$ & $.675$ & $.728$ & $.618$ \\
388	    \cmidrule(lr){1-5}
389	    2v3 & $.531$ & $.559$ & $.598^\ddagger$ & $.531$ \\
390	    3v4 & $.522$ & $.524$ & $.563$ & $.520$ \\
391	    4v5 & $.514$ & $.501$ & $.527$ & $.510$ \\
392	    \midrule
393	    $\Kempirical$ & 2 & 2 & 2 & 2 \\
394	    \bottomrule
395	    \multicolumn{5}{l}{${}^{\ddagger}$CI upper 0.606 $> \theta$; point est.\ below.} \\
396	  \end{tabular}}
397	\end{table}
398	
399	%%% Table S11: Length Ablation (exp-021)
400	\begin{table}[t]
401	  \centering
402	  \small
403	  \caption{Pairwise $\auc$ for three segment lengths (Qwen-base, cont.\ mode). $\Kempirical{=}2$ at 128/256; 512 marginal ($^\dagger$CI lower $< \theta$).}
404	  \label{tab:s11_length_ablation}
405	  \begin{tabular}{lccc}
406	    \toprule
407	    & \textbf{128} & \textbf{256} & \textbf{512} \\
408	    \midrule
409	    0v1 & .979 & .991 & .992 \\
410	    1v2 & .622 & .628 & .607$^\dagger$ \\
411	    \cmidrule(lr){1-4}
412	    2v3 & .529 & .556 & .572 \\
413	    3v4 & .535 & .530 & .530 \\
414	    4v5 & .501 & .514 & .518 \\
415	    \midrule
416	    $\Kempirical$ & 2 & 2 & 2$^\dagger$ \\
417	    \bottomrule
418	  \end{tabular}
419	\end{table}
420	
421	%%% Table S12: Domain Ablation
422	\begin{table}[t]
423	  \centering
424	  \small
425	  \caption{Pairwise $\auc$ for three text domains (Qwen-cont). arXiv yields $\Kempirical{=}3$; C4 and Wikipedia $\Kempirical{=}2$.}
426	  \label{tab:s12_domain_ablation}
427	  \begin{tabular}{lccc}
428	    \toprule
429	    & \textbf{C4} & \textbf{Wiki} & \textbf{arXiv} \\
430	    \midrule
431	    0v1 & .997 & .996 & .995 \\
432	    1v2 & .611 & .619 & .858 \\
433	    \cmidrule(lr){1-4}
434	    2v3 & .561 & .550 & .644$^*$ \\
435	    3v4 & .541 & .523 & .544 \\
436	    4v5 & .514 & .514 & .530 \\
437	    \midrule
438	    $\Kempirical$ & 2 & 2 & 3 \\
439	    \bottomrule
440	    \multicolumn{4}{l}{\footnotesize $^*$CI $[.628,.658]$; $p < 0.001$.}
441	  \end{tabular}
442	\end{table}
443	
444	%%% Table S13: Scorer Sensitivity Analysis
445	\begin{table}[t]
446	  \centering
447	  \scriptsize
448	  \caption{Scorer sensitivity: $\Kempirical$ under self- vs.\ cross-scoring. Cross-scoring reduces $\Kempirical$ only for marginal Qwen-cont.}
449	  \label{tab:s13_scorer_sensitivity}
450	  \resizebox{\columnwidth}{!}{%
451	  \begin{tabular}{llcccc}
452	    \toprule
453	    \textbf{Generator} & \textbf{Mode} & \textbf{Self} & \textbf{Pythia} & \textbf{OLMo} & \textbf{Agr.} \\
454	    \midrule
455	    Qwen-Inst & Rewrite & 2 & 2 & 2 & \checkmark \\
456	    Qwen-Inst & Cont.   & 2 & 1 & 1 & $\times$ \\
457	    Qwen-base & Cont.   & 2 & 2 & 2 & \checkmark \\
458	    Pythia    & Cont.   & 2 & 2 & 2 & \checkmark \\
459	    OLMo      & Cont.   & 1 & -- & -- & -- \\
460	    Qwen-7B   & Cont.   & 2 & -- & -- & -- \\
461	    Mistral   & Cont.   & 1 & -- & -- & -- \\
462	    \bottomrule
463	  \end{tabular}}
464	\end{table}
465	
466	\clearpage
467	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "098b3915-dcf1-4a54-a305-684300636885",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "b7033c6d-1da1-46f5-a5f8-f5c905ea08d9",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix.tex",
      "content": "\\appendix\n\\section{Supplementary Materials}\n\\label{sec:appendix}\n\nThis appendix provides supplementary figures, detailed experimental tables, dataset statistics, and complete feature descriptions referenced in the main text.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_filtering_strategies.pdf}\n\\caption{Downstream performance of all filtering strategies (5 seeds, $\\pm$1 std). Binary-ours (green) minimizes MMLU degradation; graduated $\\alpha$ sweep shows monotonic convergence toward binary. Dashed line: base model (no fine-tuning).}\n\\label{fig:filtering_strategies}\n\\end{figure}\n\n\\paragraph{Feature ranking and cross-model consistency.}\nTable~\\ref{tab:top_features} reports per-model single-feature AUC rankings.\nSurprisal derivative features (\\texttt{surp\\_d1\\_std}, \\texttt{surp\\_d2\\_std}) consistently rank among the top three across all continuation-mode models (Pythia, OLMo, Qwen-cont), with pairwise Spearman $\\rho \\geq 0.85$.\nThe rewrite-mode model (Qwen-rw) diverges by placing \\texttt{freq\\_entropy} first, reflecting a distributional shift that is lexical rather than surprisal-driven.\nThis scorer-invariant ranking supports the use of a fixed 15-dimensional feature set across generators without per-model feature selection.\n\n%%% Feature ranking table (moved from main text)\n\\begin{table}[!htbp]\n\\centering\n\\small\n\\caption{Top-3 features by single-feature $\\auc$ ranking. Bold: shared across all continuation-mode models. Spearman $\\rho$ (continuation pairs): Pythia--OLMo 0.95, Pythia--Qwen-cont 0.91, OLMo--Qwen-cont 0.85.}\n\\label{tab:top_features}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{cllll}\n\\toprule\nRank & Pythia & OLMo & Qwen-rw & Qwen-cont \\\\\n\\midrule\n1 & \\textbf{\\texttt{surp\\_d1\\_std}} & \\textbf{\\texttt{surp\\_std}} & \\texttt{freq\\_entropy} & \\textbf{\\texttt{surp\\_d1\\_std}} \\\\\n2 & \\textbf{\\texttt{surp\\_d2\\_std}} & \\textbf{\\texttt{surp\\_d1\\_std}} & \\textbf{\\texttt{surp\\_std}} & \\textbf{\\texttt{surp\\_std}} \\\\\n3 & \\textbf{\\texttt{surp\\_std}} & \\textbf{\\texttt{surp\\_d2\\_std}} & \\textbf{\\texttt{surp\\_d1\\_std}} & \\textbf{\\texttt{surp\\_d2\\_std}} \\\\\n\\bottomrule\n\\end{tabular}\n}\n\\end{table}\n\nTable~\\ref{tab:s1_transfer} reports the cross-model transfer accuracy matrix.\nClassifiers trained on continuation-mode generators (Pythia, OLMo, Qwen-cont) transfer well to each other, with off-diagonal accuracy retaining 80--92\\% of in-distribution performance.\nThe asymmetry between rewrite-mode and continuation-mode transfer (61--63\\%) confirms that generation mode, rather than model family, is the primary axis of distributional variation (Section~\\ref{sec:discussion}).\n\n%%% Table S1: Cross-Transfer Confusion Matrix (exp-013)\n\\begin{table}[!htbp]\n  \\centering\n  \\small\n  \\caption{Cross-model transfer accuracy matrix. Diagonal (\\textbf{bold}): within-model; off-diagonal: cross-model. Retention: Pythia$\\leftrightarrow$OLMo 91--92\\%, Qwen-cont$\\leftrightarrow$Pythia 83--85\\%, Qwen-rw$\\to$others 61--63\\%.}\n  \\label{tab:s1_transfer}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lcccc}\n    \\toprule\n    \\textbf{Train} & Qwen-rw & Pythia & OLMo & Qwen-cont \\\\\n    \\midrule\n    Qwen-rw   & \\textbf{.423} & .259 & .265 & .347 \\\\\n    Pythia    & .272 & \\textbf{.386} & .353 & .329 \\\\\n    OLMo      & .277 & .345 & \\textbf{.382} & .324 \\\\\n    Qwen-cont & .344 & .328 & .311 & \\textbf{.388} \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n\\paragraph{Dataset construction.}\nTable~\\ref{tab:s4_dataset_stats} summarizes the generational depth corpus.\nEach depth level contains 5{,}000 passages, yielding 30{,}000 total samples across six depths (0--5).\nDepth~0 consists of human-written seed texts from the C4 English validation split, truncated to 256 subword tokens.\nSubsequent depths are generated recursively: each depth-$k$ passage is produced by prompting the generator with the corresponding depth-$(k{-}1)$ passage.\nThe four model-mode configurations (Qwen-rw, Pythia-cont, OLMo-cont, Qwen-cont) share identical depth-0 seeds and generation pipeline, differing only in generator identity and prompting strategy (rewrite vs.\\ continuation).\n\n%%% Table S4: Dataset Statistics\n\\begin{table}[!htbp]\n  \\centering\n  \\small\n  \\caption{Dataset statistics for the generational depth corpus. Depth~0 contains human-written seed texts sampled from the C4 English validation split and truncated to 256 subword tokens. Depths~1--5 are recursively generated by Qwen2.5-1.5B-Instruct (nucleus sampling, $p{=}0.95$, $T{=}1.0$). Token counts use whitespace tokenization. Statistics shown for the primary Qwen-rewrite corpus; the other three model-mode configurations (Pythia-cont, OLMo-cont, Qwen-cont) share the same generation pipeline and corpus structure.}\n  \\label{tab:s4_dataset_stats}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{clrl}\n    \\toprule\n    \\textbf{Depth} & \\textbf{$N$ samples} & \\textbf{Mean tokens} & \\textbf{Source} \\\\\n    \\midrule\n    0 & 5{,}000 & 147.8 & C4 validation (human) \\\\\n    1 & 5{,}000 & 207.1 & Qwen2.5-1.5B rewrite \\\\\n    2 & 5{,}000 & 206.1 & Qwen2.5-1.5B rewrite \\\\\n    3 & 5{,}000 & 208.0 & Qwen2.5-1.5B rewrite \\\\\n    4 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\\\\n    5 & 5{,}000 & 207.7 & Qwen2.5-1.5B rewrite \\\\\n    \\midrule\n    \\multicolumn{2}{l}{Total} & \\multicolumn{2}{l}{30{,}000 samples} \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n%%% Table S2: Decoding Ablation AUC (exp-003)\n\\begin{table*}[t]\n  \\centering\n  \\caption{Pairwise AUC with bootstrap 95\\% CIs across depth pairs for four decoding configurations (all using Qwen2.5-1.5B-Instruct in rewrite mode; 10{,}000 bootstrap resamples). The horizontal rule between depth pairs 1\\,vs.\\,2 and 2\\,vs.\\,3 marks the empirical detectability boundary $\\Kempirical=2$. Bottom rows report cross-configuration Spearman $\\rho$ on per-feature discriminative-power rankings.}\n  \\label{tab:s2_decoding}\n  \\footnotesize\n  \\begin{tabular}{lcccc}\n    \\toprule\n    \\textbf{Depth Pair} & \\textbf{Greedy} & \\textbf{Nuc $p{=}0.9$, $T{=}1.0$} & \\textbf{Nuc $p{=}0.95$, $T{=}0.7$} & \\textbf{Nuc $p{=}0.95$, $T{=}1.2$} \\\\\n    \\midrule\n    0 vs.\\ 1 & $.980\\;[.977,\\,.982]$ & $.995\\;[.993,\\,.996]$ & $.988\\;[.986,\\,.990]$ & $.998\\;[.998,\\,.999]$ \\\\\n    1 vs.\\ 2 & $.689\\;[.680,\\,.698]$ & $.687\\;[.677,\\,.695]$ & $.689\\;[.680,\\,.697]$ & $.704\\;[.695,\\,.713]$ \\\\\n    \\cmidrule(lr){1-5}\n    2 vs.\\ 3 & $.561\\;[.552,\\,.571]$ & $.592\\;[.582,\\,.601]$\\rlap{$^\\dagger$} & $.590\\;[.581,\\,.600]$ & $.582\\;[.572,\\,.592]$ \\\\\n    3 vs.\\ 4 & $.540\\;[.531,\\,.550]$ & $.547\\;[.537,\\,.557]$ & $.539\\;[.529,\\,.549]$ & $.529\\;[.519,\\,.540]$ \\\\\n    4 vs.\\ 5 & $.514\\;[.503,\\,.524]$ & $.507\\;[.496,\\,.517]^{\\ddagger}$ & $.535\\;[.524,\\,.545]$ & $.524\\;[.513,\\,.535]$ \\\\\n    \\midrule\n    \\multicolumn{5}{l}{\\textbf{Cross-config feature Spearman $\\rho$}} \\\\\n    \\midrule\n    \\multicolumn{2}{l}{Greedy vs.\\ Nuc $p{=}0.9$} & 0.600 &\n    \\multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\\ $T{=}0.7$} & 0.782 \\\\\n    \\multicolumn{2}{l}{Greedy vs.\\ $T{=}0.7$} & 0.914 &\n    \\multicolumn{1}{l}{Nuc $p{=}0.9$ vs.\\ $T{=}1.2$} & 0.893 \\\\\n    \\multicolumn{2}{l}{Greedy vs.\\ $T{=}1.2$} & 0.532 &\n    \\multicolumn{1}{l}{$T{=}0.7$ vs.\\ $T{=}1.2$} & 0.668 \\\\\n    \\bottomrule\n    \\multicolumn{5}{l}{${}^{\\dagger}$\\,CI upper bound (0.601) marginally exceeds $\\theta{=}0.60$ by 0.001.} \\\\\n    \\multicolumn{5}{l}{${}^{\\ddagger}$\\,Permutation $p = 0.12$ (not significant). All other pairs $p < 0.01$.}\n  \\end{tabular}\n\\end{table*}\n\n%%% Table S2b: Extended K* CI (all models including new additions)\n\\begin{table*}[t]\n  \\centering\n  \\scriptsize\n  \\caption{Extended pairwise $\\auc$ with bootstrap 95\\% CIs for all model configurations including new additions.\n  This table extends Table~\\ref{tab:kstar_ci} in the main text with Qwen-base, LLaMA-8B, Mistral-7B, Pythia-6.9B (nucleus), and Gemma-2-2B configurations.\n  $\\Kempirical = 2$ holds for 6/10 conditions at $\\theta{=}0.60$ (OLMo-1B, Mistral-7B, Pythia-6.9B, Gemma-2-2B: $\\Kempirical{=}1$).}\n  \\label{tab:kstar_ci_extended}\n  \\resizebox{\\textwidth}{!}{%\n  \\begin{tabular}{lcccccccccccccccccccc}\n    \\toprule\n     & \\multicolumn{2}{c}{Qwen-rw} & \\multicolumn{2}{c}{Pythia} & \\multicolumn{2}{c}{OLMo} & \\multicolumn{2}{c}{Qwen-cont} & \\multicolumn{2}{c}{Qwen-7B\\rlap{$^\\ddagger$}} & \\multicolumn{2}{c}{Qwen-base} & \\multicolumn{2}{c}{LLaMA-8B} & \\multicolumn{2}{c}{Mistral-7B} & \\multicolumn{2}{c}{Pythia-6.9B\\rlap{$^\\S$}} & \\multicolumn{2}{c}{Gemma-2B} \\\\\n    \\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\\cmidrule(lr){6-7}\\cmidrule(lr){8-9}\\cmidrule(lr){10-11}\\cmidrule(lr){12-13}\\cmidrule(lr){14-15}\\cmidrule(lr){16-17}\\cmidrule(lr){18-19}\\cmidrule(lr){20-21}\n     & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI & $\\auc$ & 95\\% CI \\\\\n    \\midrule\n    0v1 & .9956 & & .9722 & & .9860 & & .9971 & & .9638 & [.961,\\,.967] & .987 & [.985,\\,.989] & .9224 & [.917,\\,.927] & .9170 & & .9599 & & .953 & [.949,\\,.957] \\\\\n    1v2 & .6955 & [.686,\\,.704]\\rlap{$^*$} & .6074 & [.598,\\,.617]\\rlap{$^*$} & .5001 & [.496,\\,.519] & .6112 & [.602,\\,.621]\\rlap{$^*$} & .6168 & [.608,\\,.626]\\rlap{$^*$} & .626 & [.617,\\,.635]\\rlap{$^*$} & .6123 & [.603,\\,.622]\\rlap{$^*$} & .5750 & & .5955 & & .5981 & [.588,\\,.608] \\\\\n    2v3 & .5893 & [.580,\\,.599] & .5440 & [.534,\\,.554] & .4973 & [.486,\\,.509] & .5609 & [.551,\\,.571] & .5492 & [.539,\\,.559] & .550 & [.540,\\,.560] & .5273 & [.517,\\,.538] & .5369 & & .5298 & & .534 & [.523,\\,.545] \\\\\n    3v4 & .5435 & & .5051 & & .5024 & & .5409 & & .5276 & & .529 & [.519,\\,.540] & .5168 & [.506,\\,.528] & .5174 & & .5135 & & .5033 & [.492,\\,.514] \\\\\n    4v5 & .5340 & & .5079 & & .4942 & & .5141 & & .5085 & & .518 & [.508,\\,.529] & .5159 & [.505,\\,.527] & .5175 & & ---\\rlap{$^\\|$} & & .5025 & [.492,\\,.514] \\\\\n    \\bottomrule\n    \\multicolumn{21}{l}{\\footnotesize $^*$Permutation $p < 0.001$ for all boundary comparisons.} \\\\\n    \\multicolumn{21}{l}{\\footnotesize $^\\ddagger$Generator: Qwen2.5-7B (fp16); scorer: Qwen2.5-1.5B.} \\\\\n    \\multicolumn{21}{l}{\\footnotesize $^\\|$$\\Kempirical{=}1$; 4v5 not required for boundary determination.} \\\\\n    \\multicolumn{21}{l}{\\footnotesize $^\\S$Pythia-6.9B evaluated separately; nucleus sampling ($p{=}0.95$, $T{=}1.0$), same as all other models.}\n  \\end{tabular}}% end resizebox\n\\end{table*}\n\n%%% Table S3: LLM Zero-Shot Confusion Matrices (exp-011)\n\\begin{table}[t]\n  \\centering\n  \\scriptsize\n  \\caption{LLM zero-shot depth classification: $5{\\times}5$ confusion matrices (Exp-011). Both frontier LLMs achieve high binary detection accuracy (GPT-5.5: 0.878; Claude Opus~4.6: 0.882) but near-chance 5-class accuracy (${\\sim}$0.33 vs.\\ OBD-LightGBM 0.386). Per-depth recall in Table~\\ref{tab:s3c_perdepth}.}\n  \\label{tab:s3_llm_zeroshot}\n\n  \\vspace{0.3em}\n  \\textbf{(a)} GPT-5.5 ($N{=}500$, acc${=}0.332$, MAE${=}1.102$)\n  \\vspace{1pt}\n\n  \\begin{tabular}{lcccccc}\n    \\toprule\n    & \\multicolumn{5}{c}{Predicted Depth} & \\\\\n    \\cmidrule(lr){2-6}\n    True & 0 & 1 & 2 & 3 & 4 & Rec. \\\\\n    \\midrule\n    0 & \\textbf{77} & 18 &  4 &  0 &  1 & .770 \\\\\n    1 &  9 & \\textbf{19} & 36 & 24 & 12 & .190 \\\\\n    2 &  8 & 10 & \\textbf{38} & 35 &  9 & .380 \\\\\n    3 & 10 & 16 & 35 & \\textbf{24} & 15 & .240 \\\\\n    4 & 11 & 13 & 50 & 18 &  \\textbf{8} & .080 \\\\\n    \\bottomrule\n  \\end{tabular}\n\n  \\vspace{4pt}\n  \\textbf{(b)} Claude Opus~4.6 ($N{=}499$, acc${=}0.331$, MAE${=}1.150$)\n  \\vspace{1pt}\n\n  \\begin{tabular}{lcccccc}\n    \\toprule\n    & \\multicolumn{5}{c}{Predicted Depth} & \\\\\n    \\cmidrule(lr){2-6}\n    True & 0 & 1 & 2 & 3 & 4 & Rec. \\\\\n    \\midrule\n    0 & \\textbf{69} & 26 &  3 &  0 &  2 & .690 \\\\\n    1 &  8 & \\textbf{21} & 32 & 11 & 28 & .210 \\\\\n    2 &  6 & 36 & \\textbf{28} &  5 & 25 & .280 \\\\\n    3 &  7 & 20 & 31 & \\textbf{10} & 31 & .100 \\\\\n    4 &  7 & 28 & 22 &  6 & \\textbf{37} & .370 \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n  \\centering\n  \\small\n  \\caption{Per-depth recall (\\%) on balanced $N{=}500$ test set. OBD's nominal overall accuracy gap originates from depth-0; all methods fail at depths $\\geq 2$, consistent with $\\Kempirical = 2$.}\n  \\label{tab:s3c_perdepth}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lccccc}\n    \\toprule\n    & Depth 0 & Depth 1 & Depth 2 & Depth 3 & Depth 4 \\\\\n    \\midrule\n    OBD-LightGBM & \\textbf{96} & \\textbf{39} & 14 & 19 & 22 \\\\\n    GPT-5.5      & 77 & 19 & \\textbf{38} & \\textbf{24} &  8 \\\\\n    Claude Opus~4.6 & 69 & 21 & 28 & 10 & \\textbf{37} \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n%%% Table: Token Length and EOS Truncation Analysis\n\\begin{table}[t]\n  \\centering\n  \\scriptsize\n  \\caption{Mean subword token count per depth and EOS truncation rate (\\%) for depth~1+ across all model configurations (generation limit: 256 tokens). Depth~0 (human text) is shared across configurations. Depths 1--5 show no systematic length trend; the 0v1 length asymmetry (human texts shorter) makes detection \\emph{more conservative}, not inflated. See Section~\\ref{sec:length_confound}.}\n  \\label{tab:token_length}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lcccccccc}\n    \\toprule\n    & \\multicolumn{6}{c}{\\textbf{Mean Token Count}} & & \\\\\n    \\cmidrule(lr){2-7}\n    \\textbf{Model} & D0 & D1 & D2 & D3 & D4 & D5 & \\textbf{EOS\\%} & \\textbf{Sev.} \\\\\n    \\midrule\n    Qwen-rw (1.5B)  & 191 & 254 & 252 & 254 & 254 & 254 & 7--11 & Mild \\\\\n    Pythia-1.4B      & 192 & 214 & 215 & 216 & 217 & 218 & 34--36 & High \\\\\n    OLMo-1B          & 192 & 256 & 256 & 256 & 256 & 256 & $<$1 & Negl. \\\\\n    Qwen-cont (1.5B) & 191 & 244 & 238 & 240 & 240 & 238 & 17--20 & Mod. \\\\\n    Qwen-7B          & 191 & 196 & 195 & 193 & 197 & 197 & 45--47 & High \\\\\n    \\midrule\n    \\multicolumn{9}{l}{\\textit{Decoding ablation (Qwen-rw 1.5B)}} \\\\\n    \\quad Greedy          & 191 & 253 & 252 & 253 & 254 & 254 & 8--12 & Mild \\\\\n    \\quad Nuc $p{=}0.9$   & 191 & 254 & 251 & 254 & 253 & 254 & 8--16 & Mild \\\\\n    \\quad $T{=}0.7$       & 191 & 253 & 251 & 253 & 253 & 254 & 8--14 & Mild \\\\\n    \\quad $T{=}1.2$       & 191 & 254 & 252 & 253 & 254 & 254 & 8--16 & Mild \\\\\n    \\bottomrule\n    \\multicolumn{9}{l}{EOS\\%: generation terminated via EOS before 256-token limit. Ranges span depths 1--5.}\n  \\end{tabular}}\n\\end{table}\n\n%%% Table S5: Complete 15-D Feature Descriptions\n\\begin{table*}[t]\n  \\centering\n  \\caption{Complete description of the 15-dimensional feature set used by the OBD classifier. Features are grouped into three families: surprisal statistics (9~dims) computed from Qwen2.5-1.5B token-level log-probabilities, lexical diversity (3~dims), and frequency tail shape (3~dims). All features are computed per document.}\n  \\label{tab:s5_features}\n  \\begin{tabular}{llp{0.45\\textwidth}l}\n    \\toprule\n    \\textbf{Group} & \\textbf{Feature} & \\textbf{Description} & \\textbf{Range} \\\\\n    \\midrule\n    \\multirow{9}{*}{\\rotatebox[origin=c]{90}{\\textsc{Surprisal}}}\n    & \\texttt{surp\\_mean}   & Mean token surprisal $\\frac{1}{T}\\sum_t -\\log p(x_t \\mid x_{&lt;t})$ & $\\mathbb{R}^+$ \\\\\n    & \\texttt{surp\\_std}    & Standard deviation of token surprisal & $\\mathbb{R}^+$ \\\\\n    & \\texttt{surp\\_skew}   & Skewness of the surprisal distribution & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_kurt}   & Excess kurtosis of the surprisal distribution & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d1\\_mean} & Mean of first-order surprisal differences $\\Delta s_t = s_{t+1} - s_t$ & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d1\\_std}  & Std of first-order surprisal differences & $\\mathbb{R}^+$ \\\\\n    & \\texttt{surp\\_d1\\_skew} & Skewness of first-order surprisal differences & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d2\\_mean} & Mean of second-order differences $\\Delta^2 s_t$ & $\\mathbb{R}$ \\\\\n    & \\texttt{surp\\_d2\\_std}  & Std of second-order surprisal differences & $\\mathbb{R}^+$ \\\\\n    \\midrule\n    \\multirow{3}{*}{\\rotatebox[origin=c]{90}{\\textsc{Lex}}}\n    & \\texttt{ttr}          & Type-token ratio: $|V| / T$ & $[0, 1]$ \\\\\n    & \\texttt{hapax\\_ratio} & Hapax legomena ratio: freq-1 types / unique types & $[0, 1]$ \\\\\n    & \\texttt{self\\_bleu}   & Mean 4-gram BLEU against 100 random same-depth samples & $[0, 1]$ \\\\\n    \\midrule\n    \\multirow{3}{*}{\\rotatebox[origin=c]{90}{\\textsc{Freq}}}\n    & \\texttt{freq\\_kurtosis}  & Excess kurtosis of word frequency distribution & $\\mathbb{R}$ \\\\\n    & \\texttt{freq\\_entropy}   & Shannon entropy of word frequencies: $-\\sum p_w \\log_2 p_w$ & $\\mathbb{R}^+$ \\\\\n    & \\texttt{low\\_freq\\_ratio} & Proportion of vocabulary with count $\\leq 2$ & $[0, 1]$ \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table*}\n\n%%% Tables S6 & S7: Side by side in a single table* to avoid table*/table overlap\n\\begin{table*}[t]\n\\begin{minipage}[t]{0.45\\textwidth}\n  \\centering\n  \\small\n  \\captionof{table}{LightGBM hyperparameters for the pairwise OBD (Ordinal Binary Decomposition) classifier used throughout the paper. One binary classifier is trained per adjacent depth pair $(k, k{+}1)$; 5-fold GroupKFold cross-validation is grouped by \\texttt{doc\\_id} to prevent data leakage from the same seed document appearing in both train and test.}\n  \\label{tab:s6_lgbm_params}\n  \\begin{tabular}{ll}\n    \\toprule\n    \\textbf{Parameter} & \\textbf{Value} \\\\\n    \\midrule\n    \\texttt{n\\_estimators}      & 200 \\\\\n    \\texttt{learning\\_rate}     & 0.05 \\\\\n    \\texttt{max\\_depth}         & 6 \\\\\n    \\texttt{num\\_leaves}        & 31 \\\\\n    \\texttt{verbose}            & $-1$ \\\\\n    \\texttt{n\\_jobs}            & $-1$ (all cores) \\\\\n    Cross-validation            & 5-fold GroupKFold \\\\\n    Grouping key                & \\texttt{doc\\_id} \\\\\n    Objective                   & Binary (per depth pair) \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{minipage}\\hfill\n\\begin{minipage}[t]{0.52\\textwidth}\n  \\centering\n  \\small\n  \\captionof{table}{Neural probe architecture and training details (Exp-015). Applied to all three model families (Qwen2.5-1.5B, Pythia-1.4B, OLMo-1B): each model's frozen hidden states are average-pooled into document embeddings and classified by a two-hidden-layer MLP.}\n  \\label{tab:s7_neural_probe}\n  \\resizebox{\\textwidth}{!}{%\n  \\begin{tabular}{ll}\n    \\toprule\n    \\textbf{Component} & \\textbf{Details} \\\\\n    \\midrule\n    \\multicolumn{2}{l}{\\textit{Embedding extraction}} \\\\\n    Base models       & Qwen2.5-1.5B / Pythia-1.4B / OLMo-1B (frozen) \\\\\n    Representation    & Last hidden state, attention-masked avg pool \\\\\n    Embedding dim     & 1536 / 2048 / 2048 \\\\\n    Max sequence len   & 512 tokens \\\\\n    \\midrule\n    \\multicolumn{2}{l}{\\textit{MLP classifier}} \\\\\n    Architecture      & $d_{\\text{emb}} \\to 512 \\to 256 \\to 6$ \\\\\n    Activations       & ReLU \\\\\n    Dropout           & 0.1 (after each hidden layer) \\\\\n    Output            & 6-class softmax \\\\\n    \\midrule\n    \\multicolumn{2}{l}{\\textit{Training}} \\\\\n    Optimizer         & Adam ($\\text{lr} = 10^{-3}$, weight decay $= 10^{-4}$) \\\\\n    Loss              & Cross-entropy \\\\\n    Batch size        & 256 \\\\\n    Max epochs        & 20 \\\\\n    Early stopping    & Patience = 5 (validation loss) \\\\\n    Cross-validation  & 5-fold GroupKFold \\\\\n    \\bottomrule\n  \\end{tabular}%\n  }\n\\end{minipage}\n\\end{table*}\n\n%%% Table S8: Per-Model Bootstrap CI Results (exp-007)\n\\begin{table}[t]\n  \\centering\n  \\scriptsize\n  \\caption{Pairwise AUC with bootstrap 95\\% CIs for four model-mode configurations (1{,}000 resamples). All boundary pairs ($\\auc > \\theta$) $p < 0.01$; OLMo 1v2--4v5 non-significant ($p > 0.09$).}\n  \\label{tab:s8_cv_folds}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lcccc}\n    \\toprule\n    & \\textbf{Qwen-rw} & \\textbf{Pythia} & \\textbf{OLMo} & \\textbf{Qwen-cont} \\\\\n    \\midrule\n    0v1 & $.996\\;[.995,.997]$ & $.993\\;[.992,.994]$ & $.986\\;[.984,.988]$ & $.997\\;[.996,.998]$ \\\\\n    1v2 & $.696\\;[.686,.704]$ & $.607\\;[.598,.617]$ & $.500\\;[.496,.519]$ & $.611\\;[.602,.621]$ \\\\\n    \\cmidrule(lr){1-5}\n    2v3 & $.589\\;[.580,.599]$ & $.551\\;[.542,.563]$ & $.497\\;[.486,.509]$ & $.561\\;[.551,.571]$ \\\\\n    3v4 & $.544\\;[.533,.555]$ & $.515\\;[.504,.526]$ & $.502\\;[.491,.513]$ & $.541\\;[.531,.551]$ \\\\\n    4v5 & $.534\\;[.524,.545]$ & $.514\\;[.502,.525]$ & $.494\\;[.483,.506]$ & $.514\\;[.504,.526]$ \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n%%% Table S9: Binary Detector Spearman ρ (exp-012)\n\\begin{table}[t]\n  \\centering\n  \\scriptsize\n  \\caption{Spearman $\\rho$ between binary detector scores and true depth, and 6-class accuracy. Correlations driven by 0v1; scores do not track depth beyond generation~1. Qwen-rw exhibits reversed sign ($\\rho > 0$).}\n  \\label{tab:s9_binary_spearman}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lcccc}\n    \\toprule\n    & \\textbf{Qwen-rw} & \\textbf{Pythia} & \\textbf{OLMo} & \\textbf{Qwen-cont} \\\\\n    \\midrule\n    \\multicolumn{5}{l}{\\textit{Spearman $\\rho$}} \\\\\n    \\quad log-PPL (ref)      & $-0.123$ & $-0.297$ & $-0.378$ & $-0.389$ \\\\\n    \\quad log-PPL (obs.)     & $+0.082$ & $-0.453$ & $-0.461$ & $-0.162$ \\\\\n    \\quad PPL ratio           & $+0.119$ & $-0.392$ & $-0.407$ & $-0.058$ \\\\\n    \\midrule\n    6-class acc.              & 0.199    & 0.130    & 0.127    & 0.183 \\\\\n    \\bottomrule\n    \\multicolumn{5}{l}{Random baseline: 0.167} \\\\\n  \\end{tabular}}\n\\end{table}\n\n%%% Table S10: Pythia Decoding Ablation (exp-020)\n\\begin{table}[t]\n  \\centering\n  \\scriptsize\n  \\caption{Pythia-1.4B pairwise $\\auc$ under four decoding configs (10K bootstrap). $^\\dagger$Greedy triggers repetition collapse (4-gram repeat: $d_0{=}0.01 \\to d_1{=}0.72$).}\n  \\label{tab:s10_pythia_decoding}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{lcccc}\n    \\toprule\n    & \\textbf{Greedy}$^\\dagger$ & \\textbf{$p{=}0.9$} & \\textbf{$T{=}0.7$} & \\textbf{$T{=}1.2$} \\\\\n    \\midrule\n    0v1 & $.999$ & $.995$ & $.996$ & $.994$ \\\\\n    1v2 & $.884$ & $.675$ & $.728$ & $.618$ \\\\\n    \\cmidrule(lr){1-5}\n    2v3 & $.531$ & $.559$ & $.598^\\ddagger$ & $.531$ \\\\\n    3v4 & $.522$ & $.524$ & $.563$ & $.520$ \\\\\n    4v5 & $.514$ & $.501$ & $.527$ & $.510$ \\\\\n    \\midrule\n    $\\Kempirical$ & 2 & 2 & 2 & 2 \\\\\n    \\bottomrule\n    \\multicolumn{5}{l}{${}^{\\ddagger}$CI upper 0.606 $> \\theta$; point est.\\ below.} \\\\\n  \\end{tabular}}\n\\end{table}\n\n%%% Table S11: Length Ablation (exp-021)\n\\begin{table}[t]\n  \\centering\n  \\small\n  \\caption{Pairwise $\\auc$ for three segment lengths (Qwen-base, cont.\\ mode). $\\Kempirical{=}2$ at 128/256; 512 marginal ($^\\dagger$CI lower $< \\theta$).}\n  \\label{tab:s11_length_ablation}\n  \\begin{tabular}{lccc}\n    \\toprule\n    & \\textbf{128} & \\textbf{256} & \\textbf{512} \\\\\n    \\midrule\n    0v1 & .979 & .991 & .992 \\\\\n    1v2 & .622 & .628 & .607$^\\dagger$ \\\\\n    \\cmidrule(lr){1-4}\n    2v3 & .529 & .556 & .572 \\\\\n    3v4 & .535 & .530 & .530 \\\\\n    4v5 & .501 & .514 & .518 \\\\\n    \\midrule\n    $\\Kempirical$ & 2 & 2 & 2$^\\dagger$ \\\\\n    \\bottomrule\n  \\end{tabular}\n\\end{table}\n\n%%% Table S12: Domain Ablation\n\\begin{table}[t]\n  \\centering\n  \\small\n  \\caption{Pairwise $\\auc$ for three text domains (Qwen-cont). arXiv yields $\\Kempirical{=}3$; C4 and Wikipedia $\\Kempirical{=}2$.}\n  \\label{tab:s12_domain_ablation}\n  \\begin{tabular}{lccc}\n    \\toprule\n    & \\textbf{C4} & \\textbf{Wiki} & \\textbf{arXiv} \\\\\n    \\midrule\n    0v1 & .997 & .996 & .995 \\\\\n    1v2 & .611 & .619 & .858 \\\\\n    \\cmidrule(lr){1-4}\n    2v3 & .561 & .550 & .644$^*$ \\\\\n    3v4 & .541 & .523 & .544 \\\\\n    4v5 & .514 & .514 & .530 \\\\\n    \\midrule\n    $\\Kempirical$ & 2 & 2 & 3 \\\\\n    \\bottomrule\n    \\multicolumn{4}{l}{\\footnotesize $^*$CI $[.628,.658]$; $p < 0.001$.}\n  \\end{tabular}\n\\end{table}\n\n%%% Table S13: Scorer Sensitivity Analysis\n\\begin{table}[t]\n  \\centering\n  \\scriptsize\n  \\caption{Scorer sensitivity: $\\Kempirical$ under self- vs.\\ cross-scoring. Cross-scoring reduces $\\Kempirical$ only for marginal Qwen-cont.}\n  \\label{tab:s13_scorer_sensitivity}\n  \\resizebox{\\columnwidth}{!}{%\n  \\begin{tabular}{llcccc}\n    \\toprule\n    \\textbf{Generator} & \\textbf{Mode} & \\textbf{Self} & \\textbf{Pythia} & \\textbf{OLMo} & \\textbf{Agr.} \\\\\n    \\midrule\n    Qwen-Inst & Rewrite & 2 & 2 & 2 & \\checkmark \\\\\n    Qwen-Inst & Cont.   & 2 & 1 & 1 & $\\times$ \\\\\n    Qwen-base & Cont.   & 2 & 2 & 2 & \\checkmark \\\\\n    Pythia    & Cont.   & 2 & 2 & 2 & \\checkmark \\\\\n    OLMo      & Cont.   & 1 & -- & -- & -- \\\\\n    Qwen-7B   & Cont.   & 2 & -- & -- & -- \\\\\n    Mistral   & Cont.   & 1 & -- & -- & -- \\\\\n    \\bottomrule\n  \\end{tabular}}\n\\end{table}\n\n\\clearpage\n",
      "numLines": 467,
      "startLine": 1,
      "totalLines": 467
    }
  },
  "sourceToolAssistantUUID": "098b3915-dcf1-4a54-a305-684300636885",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-23T11:01:50.387Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Hpd7KUTXu1ouJVYA464hi9`</summary>

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
  "parentUuid": "b7033c6d-1da1-46f5-a5f8-f5c905ea08d9",
  "isSidechain": false,
  "requestId": "req_011CbKPP5Pf1zgmH6Q6m6bZ1",
  "type": "assistant",
  "uuid": "de8ab475-ecc8-4237-baa6-c75a52d01335",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RH1Vc9duTAip2PnkbYXraS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 464,
      "cache_read_input_tokens": 24153,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 350,
          "cache_read_input_tokens": 24153,
          "cache_creation_input_tokens": 464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 464
          },
          "type": "message"
        }
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

_source line 20_

```json
{
  "type": "last-prompt",
  "leafUuid": "04650589-23d7-4cbb-b1dc-77bffe05da0a",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 22 · 2026-05-23T11:01:54.261Z_

<details><summary>Logged reasoning block</summary>

```text
The registry output is too large, so I need to query it with jq. Let me extract the relevant experiment data. I need to find all experiments and their AUC values to compare against the paper tables.

Let me first probe the structure of the registry file, then extract relevant experiments.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "04650589-23d7-4cbb-b1dc-77bffe05da0a",
  "isSidechain": false,
  "requestId": "req_011CbKPPQeHK2d7P9f61BeVr",
  "type": "assistant",
  "uuid": "830e421e-953b-44a9-9141-ca259bac248b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ru8NZe3pynX77hytJPZuhK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21488,
      "cache_read_input_tokens": 24617,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21488,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 24617,
          "cache_creation_input_tokens": 21488,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21488
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-23T11:01:54.783Z_

Registry output is too large. Let me extract the experiment data with jq.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "830e421e-953b-44a9-9141-ca259bac248b",
  "isSidechain": false,
  "requestId": "req_011CbKPPQeHK2d7P9f61BeVr",
  "type": "assistant",
  "uuid": "7389bba3-8d08-45c3-ac2e-9e20f74f2786",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ru8NZe3pynX77hytJPZuhK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21488,
      "cache_read_input_tokens": 24617,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21488,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 24617,
          "cache_creation_input_tokens": 21488,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21488
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-23T11:02:01.890Z_

<details open><summary>🔧 Tool call — Bash · `toolu_0127oY2cCESxCvE6xkBsy2rL`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\n# Probe structure\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = data['result']\n# result is likely a JSON string\nparsed = json.loads(result)\nprint(type(parsed).__name__, len(parsed) if isinstance(parsed, list) else 'N/A')\nif isinstance(parsed, list) and len(parsed) > 0:\n    print('Keys of first entry:', list(parsed[0].keys()))\n    print('First exp_id:', parsed[0].get('exp_id', 'N/A'))\n\"\n",
  "description": "Probe registry JSON structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7389bba3-8d08-45c3-ac2e-9e20f74f2786",
  "isSidechain": false,
  "requestId": "req_011CbKPPQeHK2d7P9f61BeVr",
  "type": "assistant",
  "uuid": "8133c4d6-e03b-4657-b2b1-75aca88aec6f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ru8NZe3pynX77hytJPZuhK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21488,
      "cache_read_input_tokens": 24617,
      "output_tokens": 408,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21488,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 408,
          "cache_read_input_tokens": 24617,
          "cache_creation_input_tokens": 21488,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21488
          },
          "type": "message"
        }
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

_source line 25 · 2026-05-23T11:02:02.090Z_

<details><summary>↩ Tool result · `toolu_0127oY2cCESxCvE6xkBsy2rL`</summary>

```text
dict N/A
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8133c4d6-e03b-4657-b2b1-75aca88aec6f",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "4628d55c-79af-4078-8743-206a0bddcdf3",
  "toolUseResult": {
    "stdout": "dict N/A",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "8133c4d6-e03b-4657-b2b1-75aca88aec6f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-23T11:02:05.914Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01KM5ZVqkLxK5C4XJiP9B1AG`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nprint(type(result).__name__)\nif isinstance(result, dict):\n    print('Top keys:', list(result.keys())[:20])\n    for k in list(result.keys())[:3]:\n        v = result[k]\n        print(f'  {k}: type={type(v).__name__}')\n        if isinstance(v, dict):\n            print(f'    keys: {list(v.keys())[:10]}')\n\"\n",
  "description": "Probe registry dict structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4628d55c-79af-4078-8743-206a0bddcdf3",
  "isSidechain": false,
  "requestId": "req_011CbKPQGPDpNL7m8vWZAhCt",
  "type": "assistant",
  "uuid": "878da136-04d8-4d09-9b0c-fa3eb156280b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YZNX2Y54BnUYXfcdpK3mPr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 46105,
      "output_tokens": 315,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 424,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 315,
          "cache_read_input_tokens": 46105,
          "cache_creation_input_tokens": 424,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 424
          },
          "type": "message"
        }
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

_source line 27 · 2026-05-23T11:02:06.023Z_

<details><summary>↩ Tool result · `toolu_01KM5ZVqkLxK5C4XJiP9B1AG`</summary>

```text
dict
Top keys: ['success', 'data', 'error', 'metadata']
  success: type=bool
  data: type=dict
    keys: ['experiments', 'count', 'total', 'baseline']
  error: type=NoneType
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "878da136-04d8-4d09-9b0c-fa3eb156280b",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "395b970a-9190-4e79-b4cf-fbedeaa04212",
  "toolUseResult": {
    "stdout": "dict\nTop keys: ['success', 'data', 'error', 'metadata']\n  success: type=bool\n  data: type=dict\n    keys: ['experiments', 'count', 'total', 'baseline']\n  error: type=NoneType",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "878da136-04d8-4d09-9b0c-fa3eb156280b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-23T11:02:09.729Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01MgogN6y4K9wUqGvP5oR1KK`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\nprint(f'Total experiments: {len(exps)}')\nprint()\nfor eid, exp in sorted(exps.items()):\n    title = exp.get('title', '')\n    status = exp.get('status', '')\n    print(f'{eid}: [{status}] {title}')\n\"\n",
  "description": "List all experiment IDs and titles"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "395b970a-9190-4e79-b4cf-fbedeaa04212",
  "isSidechain": false,
  "requestId": "req_011CbKPQZCFz79EBpe2Scaev",
  "type": "assistant",
  "uuid": "3c47d941-5646-4b5c-bc2d-967fb413901f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PAAnQrnoeWemzP3C516jAY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 389,
      "cache_read_input_tokens": 46529,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 389,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 295,
          "cache_read_input_tokens": 46529,
          "cache_creation_input_tokens": 389,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 389
          },
          "type": "message"
        }
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

_source line 29 · 2026-05-23T11:02:09.818Z_

<details><summary>↩ Tool result · `toolu_01MgogN6y4K9wUqGvP5oR1KK`</summary>

```text
Total experiments: 164

7b-cross-transfer: [PREPARING] 
arxiv_multi_source: [PREPARING] 
deberta_filter_deberta_binary: [PREPARING] 
deberta_filter_deberta_graduated: [PREPARING] 
deberta_filter_no_filter: [PREPARING] 
deberta_filter_obd_binary: [PREPARING] 
deberta_filtering_predict: [PREPARING] 
exp-008-retrain-chain: [DONE] 
exp-014: [DONE] 
exp_001_pythia_depth: [DONE] 
exp_002_olmo_depth: [DONE] 
exp_003_decoding_ablation: [DONE] 
exp_004_7b_crossscale: [DONE] 
exp_005_degradation: [DONE] 
exp_006_graduated_filtering: [DONE] 
exp_007_bootstrap_ci: [DONE] 
exp_008_retrain_chain: [PREPARING] 
exp_008_retrain_chain_v2: [DONE] 
exp_009_dose_10pct: [DONE] 
exp_009_dose_10pct_v2: [DONE] 
exp_009_dose_10pct_v3: [DONE] 
exp_009_dose_30pct: [DONE] 
exp_009_dose_30pct_v2: [DONE] 
exp_009_dose_30pct_v3: [DONE] 
exp_009_dose_50pct: [DONE] 
exp_009_dose_50pct_v2: [DONE] 
exp_009_dose_50pct_v3: [DONE] 
exp_009_dose_response: [DONE] 
exp_010_ordinal_baseline: [DONE] 
exp_011_llm_zeroshot: [DONE] 
exp_012_binary_confidence: [DONE] 
exp_013_cross_transfer: [DONE] 
exp_014_naturalistic: [DONE] 
exp_015_neural_probe: [DONE] 
exp_016_base_vs_instruct: [DONE] 
exp_017_qwen_continuation: [DONE] 
exp_018_llama8b_depth: [DONE] 
exp_019_mistral7b_depth: [DONE] 
exp_019b_mistral_cross_scorer: [DONE] 
exp_020_pythia_decoding: [DONE] 
exp_021_length_ablation: [DONE] 
exp_022_cross_scorer_matrix: [DONE] 
exp_023_domain_ablation: [DONE] 
exp_024_arxiv_domain: [DONE] 
exp_025_pythia_arxiv: [DONE] 
exp_025_pythia_filtering: [DONE] 
exp_026_arxiv_filtering: [DONE] 
exp_026_feature_stability: [DONE] 
exp_026_feature_stability_v2: [DONE] 
exp_027: [DONE] 
exp_027_latex_ablation: [DONE] 
exp_027_retrain_bootstrap: [DONE] 
exp_028_power_curve: [DONE] 
exp_028_subsampling_power: [DONE] 
exp_14b_c4: [DONE] 
exp_32b_c4: [DONE] 
exp_32b_c4_6class: [DONE] 
exp_7b_scorer_ablation: [DONE] 
exp_7b_scorer_arxiv: [DONE] 
exp_A_alt_scorer: [DONE] 
exp_B_14d_ablation: [DONE] 
exp_C_permutation_10k: [DONE] 
exp_D_obd_n500: [DONE] 
exp_E_paired_stats: [DONE] 
exp_arXiv_llama8b: [DONE] 
exp_arXiv_llama8b_crossscorer: [DONE] 
exp_arXiv_mistral7b: [DONE] 
exp_arXiv_mistral7b_crossscorer: [DONE] 
exp_arXiv_olmo: [DONE] 
exp_arXiv_qwen1b5_crossscorer: [DONE] 
exp_arXiv_qwen7b: [DONE] 
exp_arXiv_qwen7b_crossscorer: [DONE] 
exp_bootstrap_10k: [DONE] 
exp_changepoint_kstar: [DONE] 
exp_code_llama8b: [DONE] 
exp_code_mistral7b: [DONE] 
exp_code_multi_source: [DONE] 
exp_code_pythia1b4: [DONE] 
exp_code_qwen1b5: [DONE] 
exp_code_qwen1b5_pythia_scorer: [DONE] 
exp_code_qwen7b: [DONE] 
exp_contamination_rate_sweep: [DONE] 
exp_cross_transfer_llama8b_to_qwen7b: [DONE] 
exp_cross_transfer_llama8b_to_qwen7b_v2: [DONE] 
exp_cross_transfer_qwen7b_to_llama8b: [DONE] 
exp_deberta_arxiv_qwen1b5: [DONE] 
exp_deberta_c4: [DONE] 
exp_deberta_c4_1b5: [DONE] 
exp_deberta_c4_1b5_pythia: [DONE] 
exp_deberta_c4_1b5_qwen_cont: [DONE] 
exp_deberta_code_qwen1b5: [DONE] 
exp_deberta_cross_transfer_gpu1: [DONE] 
exp_deberta_cross_transfer_gpu2: [DONE] 
exp_deberta_cross_transfer_gpu3: [DONE] 
exp_deberta_cross_transfer_wiki: [DONE] 
exp_deberta_filtering_comparison: [DONE] 
exp_deberta_upperbound: [DONE] 
exp_expanded_downstream_eval: [DONE] 
exp_gemma27b_c4: [PREPARING] 
exp_gemma2b_10k: [DONE] 
exp_gemma2b_depth: [DONE] 
exp_kstar_theta: [DONE] 
exp_llama8b_10k: [DONE] 
exp_multi_source_arxiv: [DONE] 
exp_multi_source_detection: [DONE] 
exp_olmo1b_10k: [DONE] 
exp_olmo1b_c4_rerun: [DONE] 
exp_olmo_retrain_chain: [DONE] 
exp_olmo_retrain_v2: [PREPARING] 
exp_olmo_retrain_v3: [DONE] 
exp_pythia14b_10k: [DONE] 
exp_pythia14b_c4_10k: [DONE] 
exp_pythia14b_c4_rerun: [DONE] 
exp_pythia69b_c4_depth_chain: [DONE] 
exp_pythia69b_c4_depth_chain_v2: [DONE] 
exp_pythia69b_c4_depth_chain_v3: [DONE] 
exp_pythia69b_c4_nuc: [DONE] 
exp_pythia_retrain_depth7: [DONE] 
exp_qwen_cont_10k: [DONE] 
exp_qwen_retrain_chain: [DONE] 
exp_qwen_retrain_depth7: [DONE] 
exp_wiki_llama8b: [DONE] 
exp_wiki_mistral7b: [DONE] 
exp_wiki_multi_source: [DONE] 
exp_wiki_olmo: [DONE] 
exp_wiki_olmo_v2: [DONE] 
exp_wiki_pythia: [DONE] 
exp_wiki_pythia_v2: [DONE] 
exp_wiki_qwen7b: [DONE] 
exp_wiki_scorer_confound: [DONE] 
exp_wiki_scorer_confound_1b5: [DONE] 
gsm8k-serial-rerun: [PREPARING] 
gsm8k_patch_bo_s0: [PREPARING] 
gsm8k_patch_grad_s0: [PREPARING] 
gsm8k_patch_nf_s0: [PREPARING] 
mvp_pilot_sat_v1: [DONE] 
seed2_binary_ours: [PREPARING] 
seed2_graduated: [PREPARING] 
seed2_no_filter: [PREPARING] 
seed_gemma27b_c4_s42: [DONE] 
seed_pythia14b_wiki_s123: [DONE] 
seed_qwen15b_c4_s123: [DONE] 
seed_qwen15b_wiki_s123: [DONE] 
sweep_eval_r10_bin: [PREPARING] 
sweep_eval_r10_binary: [PREPARING] 
sweep_eval_r10_grad: [PREPARING] 
sweep_eval_r10_graduated: [PREPARING] 
sweep_eval_r10_nf: [PREPARING] 
sweep_eval_r10_nf_v2: [PREPARING] 
sweep_eval_r10_nofilter: [PREPARING] 
sweep_eval_r30_nf: [PREPARING] 
sweep_eval_r30_nofilter: [PREPARING] 
sweep_r100_binary: [PREPARING] 
sweep_r100_graduated: [PREPARING] 
sweep_r100_nf: [PREPARING] 
sweep_r10_binary: [PREPARING] 
sweep_r10_graduated: [PREPARING] 
sweep_r10_nofilter: [PREPARING] 
sweep_r30_binary: [PREPARING] 
sweep_r30_graduated: [PREPARING] 
sweep_r30_nofilter: [PREPARING] 
sweep_r50_binary: [PREPARING] 
sweep_r50_graduated: [PREPARING] 
sweep_r50_nf: [PREPARING]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3c47d941-5646-4b5c-bc2d-967fb413901f",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "84247e12-ea99-4864-881c-e2ba2a076486",
  "toolUseResult": {
    "stdout": "Total experiments: 164\n\n7b-cross-transfer: [PREPARING] \narxiv_multi_source: [PREPARING] \ndeberta_filter_deberta_binary: [PREPARING] \ndeberta_filter_deberta_graduated: [PREPARING] \ndeberta_filter_no_filter: [PREPARING] \ndeberta_filter_obd_binary: [PREPARING] \ndeberta_filtering_predict: [PREPARING] \nexp-008-retrain-chain: [DONE] \nexp-014: [DONE] \nexp_001_pythia_depth: [DONE] \nexp_002_olmo_depth: [DONE] \nexp_003_decoding_ablation: [DONE] \nexp_004_7b_crossscale: [DONE] \nexp_005_degradation: [DONE] \nexp_006_graduated_filtering: [DONE] \nexp_007_bootstrap_ci: [DONE] \nexp_008_retrain_chain: [PREPARING] \nexp_008_retrain_chain_v2: [DONE] \nexp_009_dose_10pct: [DONE] \nexp_009_dose_10pct_v2: [DONE] \nexp_009_dose_10pct_v3: [DONE] \nexp_009_dose_30pct: [DONE] \nexp_009_dose_30pct_v2: [DONE] \nexp_009_dose_30pct_v3: [DONE] \nexp_009_dose_50pct: [DONE] \nexp_009_dose_50pct_v2: [DONE] \nexp_009_dose_50pct_v3: [DONE] \nexp_009_dose_response: [DONE] \nexp_010_ordinal_baseline: [DONE] \nexp_011_llm_zeroshot: [DONE] \nexp_012_binary_confidence: [DONE] \nexp_013_cross_transfer: [DONE] \nexp_014_naturalistic: [DONE] \nexp_015_neural_probe: [DONE] \nexp_016_base_vs_instruct: [DONE] \nexp_017_qwen_continuation: [DONE] \nexp_018_llama8b_depth: [DONE] \nexp_019_mistral7b_depth: [DONE] \nexp_019b_mistral_cross_scorer: [DONE] \nexp_020_pythia_decoding: [DONE] \nexp_021_length_ablation: [DONE] \nexp_022_cross_scorer_matrix: [DONE] \nexp_023_domain_ablation: [DONE] \nexp_024_arxiv_domain: [DONE] \nexp_025_pythia_arxiv: [DONE] \nexp_025_pythia_filtering: [DONE] \nexp_026_arxiv_filtering: [DONE] \nexp_026_feature_stability: [DONE] \nexp_026_feature_stability_v2: [DONE] \nexp_027: [DONE] \nexp_027_latex_ablation: [DONE] \nexp_027_retrain_bootstrap: [DONE] \nexp_028_power_curve: [DONE] \nexp_028_subsampling_power: [DONE] \nexp_14b_c4: [DONE] \nexp_32b_c4: [DONE] \nexp_32b_c4_6class: [DONE] \nexp_7b_scorer_ablation: [DONE] \nexp_7b_scorer_arxiv: [DONE] \nexp_A_alt_scorer: [DONE] \nexp_B_14d_ablation: [DONE] \nexp_C_permutation_10k: [DONE] \nexp_D_obd_n500: [DONE] \nexp_E_paired_stats: [DONE] \nexp_arXiv_llama8b: [DONE] \nexp_arXiv_llama8b_crossscorer: [DONE] \nexp_arXiv_mistral7b: [DONE] \nexp_arXiv_mistral7b_crossscorer: [DONE] \nexp_arXiv_olmo: [DONE] \nexp_arXiv_qwen1b5_crossscorer: [DONE] \nexp_arXiv_qwen7b: [DONE] \nexp_arXiv_qwen7b_crossscorer: [DONE] \nexp_bootstrap_10k: [DONE] \nexp_changepoint_kstar: [DONE] \nexp_code_llama8b: [DONE] \nexp_code_mistral7b: [DONE] \nexp_code_multi_source: [DONE] \nexp_code_pythia1b4: [DONE] \nexp_code_qwen1b5: [DONE] \nexp_code_qwen1b5_pythia_scorer: [DONE] \nexp_code_qwen7b: [DONE] \nexp_contamination_rate_sweep: [DONE] \nexp_cross_transfer_llama8b_to_qwen7b: [DONE] \nexp_cross_transfer_llama8b_to_qwen7b_v2: [DONE] \nexp_cross_transfer_qwen7b_to_llama8b: [DONE] \nexp_deberta_arxiv_qwen1b5: [DONE] \nexp_deberta_c4: [DONE] \nexp_deberta_c4_1b5: [DONE] \nexp_deberta_c4_1b5_pythia: [DONE] \nexp_deberta_c4_1b5_qwen_cont: [DONE] \nexp_deberta_code_qwen1b5: [DONE] \nexp_deberta_cross_transfer_gpu1: [DONE] \nexp_deberta_cross_transfer_gpu2: [DONE] \nexp_deberta_cross_transfer_gpu3: [DONE] \nexp_deberta_cross_transfer_wiki: [DONE] \nexp_deberta_filtering_comparison: [DONE] \nexp_deberta_upperbound: [DONE] \nexp_expanded_downstream_eval: [DONE] \nexp_gemma27b_c4: [PREPARING] \nexp_gemma2b_10k: [DONE] \nexp_gemma2b_depth: [DONE] \nexp_kstar_theta: [DONE] \nexp_llama8b_10k: [DONE] \nexp_multi_source_arxiv: [DONE] \nexp_multi_source_detection: [DONE] \nexp_olmo1b_10k: [DONE] \nexp_olmo1b_c4_rerun: [DONE] \nexp_olmo_retrain_chain: [DONE] \nexp_olmo_retrain_v2: [PREPARING] \nexp_olmo_retrain_v3: [DONE] \nexp_pythia14b_10k: [DONE] \nexp_pythia14b_c4_10k: [DONE] \nexp_pythia14b_c4_rerun: [DONE] \nexp_pythia69b_c4_depth_chain: [DONE] \nexp_pythia69b_c4_depth_chain_v2: [DONE] \nexp_pythia69b_c4_depth_chain_v3: [DONE] \nexp_pythia69b_c4_nuc: [DONE] \nexp_pythia_retrain_depth7: [DONE] \nexp_qwen_cont_10k: [DONE] \nexp_qwen_retrain_chain: [DONE] \nexp_qwen_retrain_depth7: [DONE] \nexp_wiki_llama8b: [DONE] \nexp_wiki_mistral7b: [DONE] \nexp_wiki_multi_source: [DONE] \nexp_wiki_olmo: [DONE] \nexp_wiki_olmo_v2: [DONE] \nexp_wiki_pythia: [DONE] \nexp_wiki_pythia_v2: [DONE] \nexp_wiki_qwen7b: [DONE] \nexp_wiki_scorer_confound: [DONE] \nexp_wiki_scorer_confound_1b5: [DONE] \ngsm8k-serial-rerun: [PREPARING] \ngsm8k_patch_bo_s0: [PREPARING] \ngsm8k_patch_grad_s0: [PREPARING] \ngsm8k_patch_nf_s0: [PREPARING] \nmvp_pilot_sat_v1: [DONE] \nseed2_binary_ours: [PREPARING] \nseed2_graduated: [PREPARING] \nseed2_no_filter: [PREPARING] \nseed_gemma27b_c4_s42: [DONE] \nseed_pythia14b_wiki_s123: [DONE] \nseed_qwen15b_c4_s123: [DONE] \nseed_qwen15b_wiki_s123: [DONE] \nsweep_eval_r10_bin: [PREPARING] \nsweep_eval_r10_binary: [PREPARING] \nsweep_eval_r10_grad: [PREPARING] \nsweep_eval_r10_graduated: [PREPARING] \nsweep_eval_r10_nf: [PREPARING] \nsweep_eval_r10_nf_v2: [PREPARING] \nsweep_eval_r10_nofilter: [PREPARING] \nsweep_eval_r30_nf: [PREPARING] \nsweep_eval_r30_nofilter: [PREPARING] \nsweep_r100_binary: [PREPARING] \nsweep_r100_graduated: [PREPARING] \nsweep_r100_nf: [PREPARING] \nsweep_r10_binary: [PREPARING] \nsweep_r10_graduated: [PREPARING] \nsweep_r10_nofilter: [PREPARING] \nsweep_r30_binary: [PREPARING] \nsweep_r30_graduated: [PREPARING] \nsweep_r30_nofilter: [PREPARING] \nsweep_r50_binary: [PREPARING] \nsweep_r50_graduated: [PREPARING] \nsweep_r50_nf: [PREPARING]",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "3c47d941-5646-4b5c-bc2d-967fb413901f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 30 · 2026-05-23T11:02:09.820Z_

```json
{
  "parentUuid": "84247e12-ea99-4864-881c-e2ba2a076486",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "87c05387-359e-4d1a-b135-de3dece04698",
  "timestamp": "2026-05-23T11:02:09.820Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 31 · 2026-05-23T11:02:19.454Z_

<details><summary>Logged reasoning block</summary>

```text
There are 164 experiments. I need to extract the metrics (AUC values) from the relevant experiments. Let me get the data for the key experiments that correspond to Table 2 and Table 10 entries.

For Table 2 (5 configs): Qwen-rw, Pythia, OLMo, Qwen-cont, Qwen-7B
For Table 10 (10 configs): Above 5 + Qwen-base, LLaMA-8B, Mistral-7B, Pythia-6.9B, Gemma-2B

Let me extract metrics from key experiments. The relevant ones seem to be:


- exp_14b_c4: possibly Qwen related (14b might refer to 1.4B?)
- exp_001_pythia_depth: Pythia
- exp_002_olmo_depth: OLMo
- exp_017_qwen_continuation: Qwen-cont
- exp_004_7b_crossscale: Qwen-7B
- exp_016_base_vs_instruct: Qwen-base
- exp_018_llama8b_depth: LLaMA-8B
- exp_019_mistral7b_depth: Mistral-7B
- exp_pythia_6.9b: Pythia-6.9B
- exp_gemma2b_depth: Gemma-2B

Now I'm pulling the metrics from all these experiments to compare them.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "87c05387-359e-4d1a-b135-de3dece04698",
  "isSidechain": false,
  "requestId": "req_011CbKPQqVHr2Jyd7b1hjTph",
  "type": "assistant",
  "uuid": "e1412c58-9b2a-4642-9dc2-a2893a9f448e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RdyxzCj21iqiUP64d1jVUD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3063,
      "cache_read_input_tokens": 46918,
      "output_tokens": 1168,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3063,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1168,
          "cache_read_input_tokens": 46918,
          "cache_creation_input_tokens": 3063,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3063
          },
          "type": "message"
        }
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

_source line 32 · 2026-05-23T11:02:31.167Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01Uwrhnz35a2ZeY6h5A7Lu6A`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Key experiments for Table 2 and Table 10\nkey_ids = [\n    'exp_14b_c4',  # Qwen-rw?\n    'exp_001_pythia_depth',\n    'exp_002_olmo_depth', \n    'exp_017_qwen_continuation',\n    'exp_004_7b_crossscale',\n    'exp_016_base_vs_instruct',\n    'exp_018_llama8b_depth',\n    'exp_019_mistral7b_depth',\n    'exp_pythia69b_c4_nuc',\n    'exp_gemma2b_depth',\n    'exp_gemma2b_10k',\n    'exp_007_bootstrap_ci',\n    'exp_bootstrap_10k',\n    'exp_pythia14b_10k',\n    'exp_pythia14b_c4_10k',\n    'exp_pythia14b_c4_rerun',\n    'exp_olmo1b_10k',\n    'exp_olmo1b_c4_rerun',\n    'exp_qwen_cont_10k',\n    'exp_llama8b_10k',\n    'exp_pythia69b_c4_depth_chain_v3',\n    'exp_7b_scorer_ablation',\n]\n\nfor eid in key_ids:\n    if eid in exps:\n        exp = exps[eid]\n        title = exp.get('title', 'N/A')\n        metrics = exp.get('metrics', {})\n        conclusion = exp.get('conclusion', '')\n        print(f'=== {eid} ===')\n        print(f'  Title: {title}')\n        if metrics:\n            # Print all metric keys\n            print(f'  Metric keys: {list(metrics.keys())}')\n            # Print AUC-related metrics\n            for k, v in sorted(metrics.items()):\n                if 'auc' in k.lower() or 'ci' in k.lower() or 'AUC' in k:\n                    print(f'  {k}: {v}')\n        if conclusion:\n            print(f'  Conclusion: {conclusion[:200]}')\n        print()\n\" 2>&1 | head -200\n",
  "description": "Extract metrics from key experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e1412c58-9b2a-4642-9dc2-a2893a9f448e",
  "isSidechain": false,
  "requestId": "req_011CbKPQqVHr2Jyd7b1hjTph",
  "type": "assistant",
  "uuid": "b9f05177-8470-4923-9971-34e8f8c1afe2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RdyxzCj21iqiUP64d1jVUD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3063,
      "cache_read_input_tokens": 46918,
      "output_tokens": 1168,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3063,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1168,
          "cache_read_input_tokens": 46918,
          "cache_creation_input_tokens": 3063,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3063
          },
          "type": "message"
        }
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

_source line 33 · 2026-05-23T11:02:31.271Z_

<details><summary>↩ Tool result · `toolu_01Uwrhnz35a2ZeY6h5A7Lu6A`</summary>

```text
=== exp_14b_c4 ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_jsd', 'bootstrap_ci', 'permutation_p', 'k_star_statistically_confirmed', 'ordinal_mae', 'ordinal_accuracy', 'top_features', 'key_finding']
  bootstrap_ci: {'0v1': [0.9564, 0.963], '1v2': [0.6119, 0.6304], '2v3': [0.5392, 0.5594], '3v4': [0.514, 0.5346], '4v5': [0.5045, 0.5265]}
  pairwise_auc: {'0v1': 0.9598, '1v2': 0.621, '2v3': 0.5494, '3v4': 0.5243, '4v5': 0.5154}
  Conclusion: success

=== exp_001_pythia_depth ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'bootstrap_ci', 'scorer', 'note']
  bootstrap_ci: {'1v2': {'auc_oof': 0.6072, 'boot_mean': 0.6073, 'boot_std': 0.005, 'ci_95': [0.5975, 0.6172], 'ci_995_bonferroni': [0.5934, 0.621], 'perm_p': 0.0001, 'bonferroni_pass': False}}
  pairwise_auc: {'0v1': 0.9722, '1v2': 0.6074, '2v3': 0.544, '3v4': 0.5051, '4v5': 0.5079}
  pairwise_auc_std: {'0v1': 0.0039, '1v2': 0.0078, '2v3': 0.0067, '3v4': 0.0032, '4v5': 0.0101}
  Conclusion: success

=== exp_002_olmo_depth ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'scorer', 'note']
  pairwise_auc: {'0v1': 0.9861, '1v2': 0.5001, '2v3': 0.4972, '3v4': 0.5034, '4v5': 0.4971}
  Conclusion: success

=== exp_017_qwen_continuation ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_jsd', 'ordinal_mae', 'ordinal_accuracy', 'top3_features']
  pairwise_auc: {'0v1': 0.9972, '1v2': 0.6114, '2v3': 0.5609, '3v4': 0.5408, '4v5': 0.5139}
  Conclusion: success

=== exp_004_7b_crossscale ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'bootstrap_ci', 'bootstrap_resamples', 'permutation_resamples', 'pairwise_jsd', 'ordinal_mae', 'ordinal_accuracy', 'top_features', 'key_finding']
  bootstrap_ci: {'0v1': {'auc': 0.9638, 'ci_lower': 0.9607, 'ci_upper': 0.9665, 'perm_p': 0.0001}, '1v2': {'auc': 0.6168, 'ci_lower': 0.6079, 'ci_upper': 0.6261, 'perm_p': 0.0001}, '2v3': {'auc': 0.5492, 'ci_lower': 0.5388, 'ci_upper': 0.5594, 'perm_p': 0.0001}, '3v4': {'auc': 0.5276, 'ci_lower': 0.517, 'ci_upper': 0.5375, 'perm_p': 0.0001}, '4v5': {'auc': 0.5085, 'ci_lower': 0.4988, 'ci_upper': 0.5191, 'perm_p': 0.0676}}
  pairwise_auc: {'0v1': 0.9644, '1v2': 0.6178, '2v3': 0.546, '3v4': 0.5225, '4v5': 0.5091}
  pairwise_auc_std: {'0v1': 0.0034, '1v2': 0.0081, '2v3': 0.0028, '3v4': 0.0113, '4v5': 0.0052}
  Conclusion: success

=== exp_016_base_vs_instruct ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'pairwise_jsd', 'ordinal_mae', 'ordinal_accuracy', 'top_features', 'n_samples', 'bootstrap_ci', 'bootstrap_resamples', 'permutation_resamples', 'key_finding']
  bootstrap_ci: {'0v1': {'auc': 0.987, 'ci_lower': 0.9853, 'ci_upper': 0.9885, 'perm_p': 0.0001}, '1v2': {'auc': 0.626, 'ci_lower': 0.6168, 'ci_upper': 0.6353, 'perm_p': 0.0001}, '2v3': {'auc': 0.5496, 'ci_lower': 0.5397, 'ci_upper': 0.56, 'perm_p': 0.0001}, '3v4': {'auc': 0.5293, 'ci_lower': 0.5188, 'ci_upper': 0.5399, 'perm_p': 0.0001}, '4v5': {'auc': 0.5181, 'ci_lower': 0.5075, 'ci_upper': 0.5288, 'perm_p': 0.0016}}
  pairwise_auc: {'0v1': 0.987, '1v2': 0.6262, '2v3': 0.5496, '3v4': 0.5294, '4v5': 0.5182}
  pairwise_auc_std: {'0v1': 0.0015, '1v2': 0.0152, '2v3': 0.0067, '3v4': 0.0132, '4v5': 0.0139}
  Conclusion: success

=== exp_018_llama8b_depth ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'jsd', 'bootstrap_ci', 'bootstrap_resamples', 'permutation_resamples']
  bootstrap_ci: {'0v1': {'auc': 0.9224, 'ci_lower': 0.9174, 'ci_upper': 0.9272, 'perm_p': 0.0001}, '1v2': {'auc': 0.6123, 'ci_lower': 0.6028, 'ci_upper': 0.6216, 'perm_p': 0.0001}, '2v3': {'auc': 0.5273, 'ci_lower': 0.5169, 'ci_upper': 0.5378, 'perm_p': 0.0001}, '3v4': {'auc': 0.5168, 'ci_lower': 0.5062, 'ci_upper': 0.5275, 'perm_p': 0.0037}, '4v5': {'auc': 0.5159, 'ci_lower': 0.5052, 'ci_upper': 0.5268, 'perm_p': 0.0035}}
  pairwise_auc: {'0v1': 0.9225, '1v2': 0.6123, '2v3': 0.5274, '3v4': 0.5138, '4v5': 0.5097}
  Conclusion: success

=== exp_019_mistral7b_depth ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'bootstrap_ci_1v2', 'jsd', 'ordinal_mae', 'ordinal_accuracy', 'top3_features']
  bootstrap_ci_1v2: {'ci_lower': 0.5835, 'ci_upper': 0.6032, 'p_auc_leq_060': 0.9017}
  pairwise_auc: {'0v1': 0.9843, '1v2': 0.5935, '2v3': 0.5402, '3v4': 0.5232, '4v5': 0.5181}
  Conclusion: success

=== exp_pythia69b_c4_nuc ===
  Title: N/A
  Metric keys: ['K_star', 'pairwise_auc', 'scorer', 'theta', 'note']
  pairwise_auc: {'0v1': 0.9599, '1v2': 0.5955, '2v3': 0.5298, '3v4': 0.5135}
  Conclusion: negative

=== exp_gemma2b_depth ===
  Title: N/A
  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'bootstrap_ci_1v2', 'jsd', 'ordinal_mae', 'ordinal_accuracy', 'note']
  bootstrap_ci_1v2: {'ci_lower': 0.5882, 'ci_upper': 0.6076}
  pairwise_auc: {'0v1': 0.9534, '1v2': 0.5981, '2v3': 0.5342, '3v4': 0.503, '4v5': 0.5026}
  pairwise_auc_std: {'0v1': 0.003, '1v2': 0.008, '2v3': 0.013, '3v4': 0.003, '4v5': 0.013}
  Conclusion: negative

=== exp_gemma2b_10k ===
  Title: N/A
  Metric keys: ['K_star_self', 'K_star_qwen', 'scorer', 'pairwise_auc_self', 'pairwise_auc_qwen', 'bootstrap_ci_1v2', 'note']
  bootstrap_ci_1v2: {'auc_oof': 0.6099, 'boot_std': 0.0034, 'ci_95': [0.6031, 0.6167], 'ci_995_bonferroni_pct': [0.5998, 0.6192], 'ci_995_bonferroni_norm': [0.6003, 0.6196], 'perm_p': 0.0001, 'bonferroni_pass_pct': False, 'bonferroni_pass_norm': True}
  pairwise_auc_qwen: {'0v1': 0.9533, '1v2': 0.6099, '2v3': 0.5409, '3v4': 0.5174, '4v5': 0.5158}
  pairwise_auc_self: {'0v1': 0.9817, '1v2': 0.643, '2v3': 0.555, '3v4': 0.5173, '4v5': 0.5101}
  Conclusion: success

=== exp_007_bootstrap_ci ===
  Title: N/A
  Metric keys: ['qwen_rewrite', 'pythia_cont', 'olmo_cont', 'qwen_cont', 'k_star_robust', 'all_1v2_ci_lower_above_060', 'most_marginal']
  all_1v2_ci_lower_above_060: True
  Conclusion: success

=== exp_bootstrap_10k ===
  Title: N/A
  Metric keys: ['configs_tested', 'configs_missing', 'results', 'missing', 'conclusion']
  Conclusion: success

=== exp_pythia14b_10k ===
  Title: N/A
  Conclusion: killed

=== exp_pythia14b_c4_10k ===
  Title: N/A
  Metric keys: ['K_star', 'AUC_0v1', 'AUC_1v2', 'AUC_2v3', 'AUC_3v4', 'AUC_4v5', 'bootstrap_1v2_95CI', 'bootstrap_1v2_995CI_bonferroni', 'perm_pvalue_1v2', 'bonferroni_pass', 'top_feature']
  AUC_0v1: 0.9712
  AUC_1v2: 0.6175
  AUC_2v3: 0.5364
  AUC_3v4: 0.5134
  AUC_4v5: 0.5088
  bootstrap_1v2_95CI: [0.6108, 0.6242]
  bootstrap_1v2_995CI_bonferroni: [0.6078, 0.6273]
  Conclusion: success

=== exp_pythia14b_c4_rerun ===
  Title: N/A
  Metric keys: ['0v1_auc', '1v2_auc', '2v3_auc', '3v4_auc', '4v5_auc', 'kstar_at_060', '0v1_jsd', '1v2_jsd', 'NOTE']
  0v1_auc: 0.9979
  1v2_auc: 0.8786
  2v3_auc: 0.5399
  3v4_auc: 0.5062
  4v5_auc: 0.5025
  Conclusion: negative

=== exp_olmo1b_10k ===
  Title: N/A
  Metric keys: ['pairwise_auc', 'K_star', 'ordinal_mae', 'ordinal_accuracy', 'pairwise_jsd', 'top_features']
  pairwise_auc: {'0v1': 0.9871, '1v2': 0.4984, '2v3': 0.5059, '3v4': 0.5061, '4v5': 0.5074}
  Conclusion: success

=== exp_olmo1b_c4_rerun ===
  Title: N/A
  Metric keys: ['0v1_auc', '1v2_auc', '2v3_auc', '3v4_auc', '4v5_auc', 'kstar_at_060', 'main_table_1v2', 'delta']
  0v1_auc: 0.986
  1v2_auc: 0.508
  2v3_auc: 0.4973
  3v4_auc: 0.5024
  4v5_auc: 0.4942
  Conclusion: negative

=== exp_qwen_cont_10k ===
  Title: N/A
  Metric keys: ['K_star', 'AUC_0v1', 'AUC_1v2', 'AUC_2v3', 'AUC_3v4', 'AUC_4v5', 'bootstrap_1v2_95CI', 'bootstrap_1v2_995CI_bonferroni', 'perm_pvalue_1v2', 'bonferroni_pass', 'top_feature']
  AUC_0v1: 0.9875
  AUC_1v2: 0.6346
  AUC_2v3: 0.5616
  AUC_3v4: 0.5451
  AUC_4v5: 0.5254
  bootstrap_1v2_95CI: [0.6282, 0.6409]
  bootstrap_1v2_995CI_bonferroni: [0.6255, 0.6436]
  Conclusion: success

=== exp_llama8b_10k ===
  Title: N/A
  Metric keys: ['K_star', 'AUC_0v1', 'AUC_1v2', 'AUC_1v2_oof', 'AUC_2v3', 'AUC_3v4', 'AUC_4v5', 'bootstrap_1v2_oof_auc', 'bootstrap_1v2_95CI', 'bootstrap_1v2_995CI_bonferroni', 'bonferroni_pass', 'perm_pvalue_1v2', 'scorer', 'note']
  AUC_0v1: 0.9282
  AUC_1v2: 0.6148
  AUC_1v2_oof: 0.588
  AUC_2v3: 0.5247
  AUC_3v4: 0.5519
  AUC_4v5: 0.5262
  bootstrap_1v2_95CI: [0.5809, 0.595]
  bootstrap_1v2_995CI_bonferroni: [0.5776, 0.5978]
  bootstrap_1v2_oof_auc: 0.588
  Conclusion: negative

=== exp_pythia69b_c4_depth_chain_v3 ===
  Title: N/A
  Metric keys: ['0v1_auc', '1v2_auc', '2v3_auc', '3v4_auc', '4v5_auc', 'kstar_at_060', '0v1_jsd', '1v2_jsd', '2v3_jsd', 'empty_texts_total', 'features_rows']
  0v1_auc: 0.9941
  1v2_auc: 0.8542
  2v3_auc: 0.5373
  3v4_auc: 0.5339
  4v5_auc: 0.5211
  Conclusion: negative

=== exp_7b_scorer_ablation ===
  Title: N/A
  Metric keys: ['pythia_c4__qwen1.5b', 'olmo_c4__qwen1.5b', 'pythia_c4__qwen7b', 'olmo_c4__qwen7b', 'match']
  Conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b9f05177-8470-4923-9971-34e8f8c1afe2",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "9da26e27-8517-4d18-94ec-70dd1ada9139",
  "toolUseResult": {
    "stdout": "=== exp_14b_c4 ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_jsd', 'bootstrap_ci', 'permutation_p', 'k_star_statistically_confirmed', 'ordinal_mae', 'ordinal_accuracy', 'top_features', 'key_finding']\n  bootstrap_ci: {'0v1': [0.9564, 0.963], '1v2': [0.6119, 0.6304], '2v3': [0.5392, 0.5594], '3v4': [0.514, 0.5346], '4v5': [0.5045, 0.5265]}\n  pairwise_auc: {'0v1': 0.9598, '1v2': 0.621, '2v3': 0.5494, '3v4': 0.5243, '4v5': 0.5154}\n  Conclusion: success\n\n=== exp_001_pythia_depth ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'bootstrap_ci', 'scorer', 'note']\n  bootstrap_ci: {'1v2': {'auc_oof': 0.6072, 'boot_mean': 0.6073, 'boot_std': 0.005, 'ci_95': [0.5975, 0.6172], 'ci_995_bonferroni': [0.5934, 0.621], 'perm_p': 0.0001, 'bonferroni_pass': False}}\n  pairwise_auc: {'0v1': 0.9722, '1v2': 0.6074, '2v3': 0.544, '3v4': 0.5051, '4v5': 0.5079}\n  pairwise_auc_std: {'0v1': 0.0039, '1v2': 0.0078, '2v3': 0.0067, '3v4': 0.0032, '4v5': 0.0101}\n  Conclusion: success\n\n=== exp_002_olmo_depth ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'scorer', 'note']\n  pairwise_auc: {'0v1': 0.9861, '1v2': 0.5001, '2v3': 0.4972, '3v4': 0.5034, '4v5': 0.4971}\n  Conclusion: success\n\n=== exp_017_qwen_continuation ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_jsd', 'ordinal_mae', 'ordinal_accuracy', 'top3_features']\n  pairwise_auc: {'0v1': 0.9972, '1v2': 0.6114, '2v3': 0.5609, '3v4': 0.5408, '4v5': 0.5139}\n  Conclusion: success\n\n=== exp_004_7b_crossscale ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'bootstrap_ci', 'bootstrap_resamples', 'permutation_resamples', 'pairwise_jsd', 'ordinal_mae', 'ordinal_accuracy', 'top_features', 'key_finding']\n  bootstrap_ci: {'0v1': {'auc': 0.9638, 'ci_lower': 0.9607, 'ci_upper': 0.9665, 'perm_p': 0.0001}, '1v2': {'auc': 0.6168, 'ci_lower': 0.6079, 'ci_upper': 0.6261, 'perm_p': 0.0001}, '2v3': {'auc': 0.5492, 'ci_lower': 0.5388, 'ci_upper': 0.5594, 'perm_p': 0.0001}, '3v4': {'auc': 0.5276, 'ci_lower': 0.517, 'ci_upper': 0.5375, 'perm_p': 0.0001}, '4v5': {'auc': 0.5085, 'ci_lower': 0.4988, 'ci_upper': 0.5191, 'perm_p': 0.0676}}\n  pairwise_auc: {'0v1': 0.9644, '1v2': 0.6178, '2v3': 0.546, '3v4': 0.5225, '4v5': 0.5091}\n  pairwise_auc_std: {'0v1': 0.0034, '1v2': 0.0081, '2v3': 0.0028, '3v4': 0.0113, '4v5': 0.0052}\n  Conclusion: success\n\n=== exp_016_base_vs_instruct ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'pairwise_jsd', 'ordinal_mae', 'ordinal_accuracy', 'top_features', 'n_samples', 'bootstrap_ci', 'bootstrap_resamples', 'permutation_resamples', 'key_finding']\n  bootstrap_ci: {'0v1': {'auc': 0.987, 'ci_lower': 0.9853, 'ci_upper': 0.9885, 'perm_p': 0.0001}, '1v2': {'auc': 0.626, 'ci_lower': 0.6168, 'ci_upper': 0.6353, 'perm_p': 0.0001}, '2v3': {'auc': 0.5496, 'ci_lower': 0.5397, 'ci_upper': 0.56, 'perm_p': 0.0001}, '3v4': {'auc': 0.5293, 'ci_lower': 0.5188, 'ci_upper': 0.5399, 'perm_p': 0.0001}, '4v5': {'auc': 0.5181, 'ci_lower': 0.5075, 'ci_upper': 0.5288, 'perm_p': 0.0016}}\n  pairwise_auc: {'0v1': 0.987, '1v2': 0.6262, '2v3': 0.5496, '3v4': 0.5294, '4v5': 0.5182}\n  pairwise_auc_std: {'0v1': 0.0015, '1v2': 0.0152, '2v3': 0.0067, '3v4': 0.0132, '4v5': 0.0139}\n  Conclusion: success\n\n=== exp_018_llama8b_depth ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'jsd', 'bootstrap_ci', 'bootstrap_resamples', 'permutation_resamples']\n  bootstrap_ci: {'0v1': {'auc': 0.9224, 'ci_lower': 0.9174, 'ci_upper': 0.9272, 'perm_p': 0.0001}, '1v2': {'auc': 0.6123, 'ci_lower': 0.6028, 'ci_upper': 0.6216, 'perm_p': 0.0001}, '2v3': {'auc': 0.5273, 'ci_lower': 0.5169, 'ci_upper': 0.5378, 'perm_p': 0.0001}, '3v4': {'auc': 0.5168, 'ci_lower': 0.5062, 'ci_upper': 0.5275, 'perm_p': 0.0037}, '4v5': {'auc': 0.5159, 'ci_lower': 0.5052, 'ci_upper': 0.5268, 'perm_p': 0.0035}}\n  pairwise_auc: {'0v1': 0.9225, '1v2': 0.6123, '2v3': 0.5274, '3v4': 0.5138, '4v5': 0.5097}\n  Conclusion: success\n\n=== exp_019_mistral7b_depth ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'bootstrap_ci_1v2', 'jsd', 'ordinal_mae', 'ordinal_accuracy', 'top3_features']\n  bootstrap_ci_1v2: {'ci_lower': 0.5835, 'ci_upper': 0.6032, 'p_auc_leq_060': 0.9017}\n  pairwise_auc: {'0v1': 0.9843, '1v2': 0.5935, '2v3': 0.5402, '3v4': 0.5232, '4v5': 0.5181}\n  Conclusion: success\n\n=== exp_pythia69b_c4_nuc ===\n  Title: N/A\n  Metric keys: ['K_star', 'pairwise_auc', 'scorer', 'theta', 'note']\n  pairwise_auc: {'0v1': 0.9599, '1v2': 0.5955, '2v3': 0.5298, '3v4': 0.5135}\n  Conclusion: negative\n\n=== exp_gemma2b_depth ===\n  Title: N/A\n  Metric keys: ['k_star', 'pairwise_auc', 'pairwise_auc_std', 'bootstrap_ci_1v2', 'jsd', 'ordinal_mae', 'ordinal_accuracy', 'note']\n  bootstrap_ci_1v2: {'ci_lower': 0.5882, 'ci_upper': 0.6076}\n  pairwise_auc: {'0v1': 0.9534, '1v2': 0.5981, '2v3': 0.5342, '3v4': 0.503, '4v5': 0.5026}\n  pairwise_auc_std: {'0v1': 0.003, '1v2': 0.008, '2v3': 0.013, '3v4': 0.003, '4v5': 0.013}\n  Conclusion: negative\n\n=== exp_gemma2b_10k ===\n  Title: N/A\n  Metric keys: ['K_star_self', 'K_star_qwen', 'scorer', 'pairwise_auc_self', 'pairwise_auc_qwen', 'bootstrap_ci_1v2', 'note']\n  bootstrap_ci_1v2: {'auc_oof': 0.6099, 'boot_std': 0.0034, 'ci_95': [0.6031, 0.6167], 'ci_995_bonferroni_pct': [0.5998, 0.6192], 'ci_995_bonferroni_norm': [0.6003, 0.6196], 'perm_p': 0.0001, 'bonferroni_pass_pct': False, 'bonferroni_pass_norm': True}\n  pairwise_auc_qwen: {'0v1': 0.9533, '1v2': 0.6099, '2v3': 0.5409, '3v4': 0.5174, '4v5': 0.5158}\n  pairwise_auc_self: {'0v1': 0.9817, '1v2': 0.643, '2v3': 0.555, '3v4': 0.5173, '4v5': 0.5101}\n  Conclusion: success\n\n=== exp_007_bootstrap_ci ===\n  Title: N/A\n  Metric keys: ['qwen_rewrite', 'pythia_cont', 'olmo_cont', 'qwen_cont', 'k_star_robust', 'all_1v2_ci_lower_above_060', 'most_marginal']\n  all_1v2_ci_lower_above_060: True\n  Conclusion: success\n\n=== exp_bootstrap_10k ===\n  Title: N/A\n  Metric keys: ['configs_tested', 'configs_missing', 'results', 'missing', 'conclusion']\n  Conclusion: success\n\n=== exp_pythia14b_10k ===\n  Title: N/A\n  Conclusion: killed\n\n=== exp_pythia14b_c4_10k ===\n  Title: N/A\n  Metric keys: ['K_star', 'AUC_0v1', 'AUC_1v2', 'AUC_2v3', 'AUC_3v4', 'AUC_4v5', 'bootstrap_1v2_95CI', 'bootstrap_1v2_995CI_bonferroni', 'perm_pvalue_1v2', 'bonferroni_pass', 'top_feature']\n  AUC_0v1: 0.9712\n  AUC_1v2: 0.6175\n  AUC_2v3: 0.5364\n  AUC_3v4: 0.5134\n  AUC_4v5: 0.5088\n  bootstrap_1v2_95CI: [0.6108, 0.6242]\n  bootstrap_1v2_995CI_bonferroni: [0.6078, 0.6273]\n  Conclusion: success\n\n=== exp_pythia14b_c4_rerun ===\n  Title: N/A\n  Metric keys: ['0v1_auc', '1v2_auc', '2v3_auc', '3v4_auc', '4v5_auc', 'kstar_at_060', '0v1_jsd', '1v2_jsd', 'NOTE']\n  0v1_auc: 0.9979\n  1v2_auc: 0.8786\n  2v3_auc: 0.5399\n  3v4_auc: 0.5062\n  4v5_auc: 0.5025\n  Conclusion: negative\n\n=== exp_olmo1b_10k ===\n  Title: N/A\n  Metric keys: ['pairwise_auc', 'K_star', 'ordinal_mae', 'ordinal_accuracy', 'pairwise_jsd', 'top_features']\n  pairwise_auc: {'0v1': 0.9871, '1v2': 0.4984, '2v3': 0.5059, '3v4': 0.5061, '4v5': 0.5074}\n  Conclusion: success\n\n=== exp_olmo1b_c4_rerun ===\n  Title: N/A\n  Metric keys: ['0v1_auc', '1v2_auc', '2v3_auc', '3v4_auc', '4v5_auc', 'kstar_at_060', 'main_table_1v2', 'delta']\n  0v1_auc: 0.986\n  1v2_auc: 0.508\n  2v3_auc: 0.4973\n  3v4_auc: 0.5024\n  4v5_auc: 0.4942\n  Conclusion: negative\n\n=== exp_qwen_cont_10k ===\n  Title: N/A\n  Metric keys: ['K_star', 'AUC_0v1', 'AUC_1v2', 'AUC_2v3', 'AUC_3v4', 'AUC_4v5', 'bootstrap_1v2_95CI', 'bootstrap_1v2_995CI_bonferroni', 'perm_pvalue_1v2', 'bonferroni_pass', 'top_feature']\n  AUC_0v1: 0.9875\n  AUC_1v2: 0.6346\n  AUC_2v3: 0.5616\n  AUC_3v4: 0.5451\n  AUC_4v5: 0.5254\n  bootstrap_1v2_95CI: [0.6282, 0.6409]\n  bootstrap_1v2_995CI_bonferroni: [0.6255, 0.6436]\n  Conclusion: success\n\n=== exp_llama8b_10k ===\n  Title: N/A\n  Metric keys: ['K_star', 'AUC_0v1', 'AUC_1v2', 'AUC_1v2_oof', 'AUC_2v3', 'AUC_3v4', 'AUC_4v5', 'bootstrap_1v2_oof_auc', 'bootstrap_1v2_95CI', 'bootstrap_1v2_995CI_bonferroni', 'bonferroni_pass', 'perm_pvalue_1v2', 'scorer', 'note']\n  AUC_0v1: 0.9282\n  AUC_1v2: 0.6148\n  AUC_1v2_oof: 0.588\n  AUC_2v3: 0.5247\n  AUC_3v4: 0.5519\n  AUC_4v5: 0.5262\n  bootstrap_1v2_95CI: [0.5809, 0.595]\n  bootstrap_1v2_995CI_bonferroni: [0.5776, 0.5978]\n  bootstrap_1v2_oof_auc: 0.588\n  Conclusion: negative\n\n=== exp_pythia69b_c4_depth_chain_v3 ===\n  Title: N/A\n  Metric keys: ['0v1_auc', '1v2_auc', '2v3_auc', '3v4_auc', '4v5_auc', 'kstar_at_060', '0v1_jsd', '1v2_jsd', '2v3_jsd', 'empty_texts_total', 'features_rows']\n  0v1_auc: 0.9941\n  1v2_auc: 0.8542\n  2v3_auc: 0.5373\n  3v4_auc: 0.5339\n  4v5_auc: 0.5211\n  Conclusion: negative\n\n=== exp_7b_scorer_ablation ===\n  Title: N/A\n  Metric keys: ['pythia_c4__qwen1.5b', 'olmo_c4__qwen1.5b', 'pythia_c4__qwen7b', 'olmo_c4__qwen7b', 'match']\n  Conclusion: success",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "b9f05177-8470-4923-9971-34e8f8c1afe2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 34_

```json
{
  "type": "last-prompt",
  "leafUuid": "9da26e27-8517-4d18-94ec-70dd1ada9139",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 35_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 36 · 2026-05-23T11:03:04.962Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to figure out which experiments map to which paper table entries. Let me also check Mistral and some other specific data. I also need to understand which registry experiments are the canonical ones used in the paper.

Let me extract more specific data, especially for Qwen-rw (the main Qwen rewrite configuration). The `exp_14b_c4` doesn't seem right for Qwen-rw since the AUCs don't match. Let me look for Qwen-rw specific experiments and also get the detailed bootstrap CI data.

For Table 2 and Table 10, the paper values are:


**Qwen-rw**: 0v1=.9956, 1v2=.6955 [.686,.704], 2v3=.5893 [.580,.599], 3v4=.5435, 4v5=.5340
**Pythia**: 0v1=.9722, 1v2=.6074 [.598,.617], 2v3=.5440 [.534,.554], 3v4=.5051, 4v5=.5079
**OLMo**: 0v1=.9860, 1v2=.5001 [.496,.519], 2v3=.4

973 [.486,.509], 3v4=.5024, 4v5=.4942
**Qwen-cont**: 0v1=.9971, 1v2=.6112 [.602,.621], 2v3=.5609 [.551,.571], 3v4=.5409, 4v5=.5141
**Qwen-7B**: 0v1=.9638 [.961,.967], 1v2=.6168 [.608,.626], 2v3=.5492 [.539,.559], 3v4=.5276, 4v5=.5085

Now I'm cross-checking the registry values against what I've collected, particularly for Pythia to verify the consistency of the depth metrics.

Looking at OLMo's results, I'm noticing some discrepancies between the paper values and what's in the registry for the later layer comparisons, but when I check the rerun experiment, those values align perfectly with what the paper reports. The 4v5 result of 0.4942 in the rerun matches the paper, while exp_002 shows 0.4971, so the paper definitely uses the rerun experiment for OLMo. The discrepancy in the 0v1 value (0.986 vs 0.9860) might just be a rounding difference—the stored value could have more precision than displayed.

Now I'm searching through the Qwen experiments to find the right match. The exp_14b_c4 values don't align with Qwen-rw at all, but exp_016_base_vs_instruct shows 0v1=0.987 and 1v2=0.626, which correspond to the Qwen-base results in Table 10.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9da26e27-8517-4d18-94ec-70dd1ada9139",
  "isSidechain": false,
  "requestId": "req_011CbKPSRAd8oktiJ7b6hZNE",
  "type": "assistant",
  "uuid": "2dddc1a0-0ad4-480f-89c3-ee27be60821c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015gRzauUsHWYGiBZC5kPsHV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6190,
      "cache_read_input_tokens": 49981,
      "output_tokens": 2024,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6190,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2024,
          "cache_read_input_tokens": 49981,
          "cache_creation_input_tokens": 6190,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6190
          },
          "type": "message"
        }
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

_source line 37 · 2026-05-23T11:03:12.393Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01XYm4VAH8dGhkP1iNTUZbZT`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Find Qwen-rw related experiments - search by AUC values near .9956 and .6955\nfor eid, exp in sorted(exps.items()):\n    metrics = exp.get('metrics', {})\n    pauc = metrics.get('pairwise_auc', {})\n    if isinstance(pauc, dict):\n        v01 = pauc.get('0v1', None)\n        v12 = pauc.get('1v2', None)\n        if v01 and v12:\n            if (0.99 < v01 < 1.0 and 0.68 < v12 < 0.72):\n                print(f'{eid}: 0v1={v01}, 1v2={v12}')\n                print(f'  All AUC: {pauc}')\n                ci = metrics.get('bootstrap_ci', {})\n                if ci:\n                    print(f'  Bootstrap CI: {json.dumps(ci, indent=2)[:500]}')\n                print()\n\" 2>&1\n",
  "description": "Find Qwen-rw experiment by AUC pattern"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2dddc1a0-0ad4-480f-89c3-ee27be60821c",
  "isSidechain": false,
  "requestId": "req_011CbKPSRAd8oktiJ7b6hZNE",
  "type": "assistant",
  "uuid": "85d4cb4b-432f-4d84-ab62-8f83992f522d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015gRzauUsHWYGiBZC5kPsHV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6190,
      "cache_read_input_tokens": 49981,
      "output_tokens": 2024,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6190,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2024,
          "cache_read_input_tokens": 49981,
          "cache_creation_input_tokens": 6190,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6190
          },
          "type": "message"
        }
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

_source line 38 · 2026-05-23T11:03:12.612Z_

<details><summary>↩ Tool result · reported error · `toolu_01XYm4VAH8dGhkP1iNTUZbZT`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 15, in &lt;module>
    if (0.99 < v01 < 1.0 and 0.68 < v12 < 0.72):
        ^^^^^^^^^^^^^^^^
TypeError: '<' not supported between instances of 'float' and 'dict'
exp_32b_c4_6class: 0v1=0.9923, 1v2=0.6945
  All AUC: {'0v1': 0.9923, '1v2': 0.6945, '2v3': 0.5978, '3v4': 0.5669, '4v5': 0.5426}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "85d4cb4b-432f-4d84-ab62-8f83992f522d",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "3c31380e-2e03-4fb2-88ce-75e29dfd90ed",
  "toolUseResult": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 15, in &lt;module>\n    if (0.99 < v01 < 1.0 and 0.68 < v12 < 0.72):\n        ^^^^^^^^^^^^^^^^\nTypeError: '<' not supported between instances of 'float' and 'dict'\nexp_32b_c4_6class: 0v1=0.9923, 1v2=0.6945\n  All AUC: {'0v1': 0.9923, '1v2': 0.6945, '2v3': 0.5978, '3v4': 0.5669, '4v5': 0.5426}",
  "sourceToolAssistantUUID": "85d4cb4b-432f-4d84-ab62-8f83992f522d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-23T11:03:18.252Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01HPtzcqefLZTmgVH7JvUDRs`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Find Qwen-rw: search for 0v1 near .9956 and 1v2 near .6955\nfor eid, exp in sorted(exps.items()):\n    metrics = exp.get('metrics', {})\n    pauc = metrics.get('pairwise_auc', {})\n    if isinstance(pauc, dict):\n        v01 = pauc.get('0v1', None)\n        v12 = pauc.get('1v2', None)\n        if v01 is None or v12 is None:\n            continue\n        if not isinstance(v01, (int, float)) or not isinstance(v12, (int, float)):\n            continue\n        if (0.99 < v01 < 1.0 and 0.68 < v12 < 0.72):\n            print(f'{eid}: 0v1={v01}, 1v2={v12}')\n            print(f'  All AUC: {pauc}')\n            ci = metrics.get('bootstrap_ci', {})\n            if ci:\n                print(f'  Bootstrap CI keys: {list(ci.keys())}')\n            print()\n\" 2>&1\n",
  "description": "Find Qwen-rw experiment by AUC values"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c31380e-2e03-4fb2-88ce-75e29dfd90ed",
  "isSidechain": false,
  "requestId": "req_011CbKPVTtujkFeLoafgZhrr",
  "type": "assistant",
  "uuid": "d48caeda-225f-4ff9-b89d-9812631ab74c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SCeSSksPqzDJhXrKEGAz7C",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2219,
      "cache_read_input_tokens": 56171,
      "output_tokens": 521,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2219,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 521,
          "cache_read_input_tokens": 56171,
          "cache_creation_input_tokens": 2219,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2219
          },
          "type": "message"
        }
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

_source line 40 · 2026-05-23T11:03:18.367Z_

<details><summary>↩ Tool result · `toolu_01HPtzcqefLZTmgVH7JvUDRs`</summary>

```text
exp_32b_c4_6class: 0v1=0.9923, 1v2=0.6945
  All AUC: {'0v1': 0.9923, '1v2': 0.6945, '2v3': 0.5978, '3v4': 0.5669, '4v5': 0.5426}

exp_deberta_c4_1b5: 0v1=0.9923, 1v2=0.7052
  All AUC: {'0v1': 0.9923, '1v2': 0.7052, '2v3': 0.5988, '3v4': 0.5698, '4v5': 0.5475}

exp_deberta_c4_1b5_qwen_cont: 0v1=0.9955, 1v2=0.7194
  All AUC: {'0v1': 0.9955, '1v2': 0.7194, '2v3': 0.5954, '3v4': 0.5689, '4v5': 0.5502}

mvp_pilot_sat_v1: 0v1=0.9956, 1v2=0.6957
  All AUC: {'0v1': 0.9956, '1v2': 0.6957, '2v3': 0.5893, '3v4': 0.5434, '4v5': 0.5343}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d48caeda-225f-4ff9-b89d-9812631ab74c",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "32cfba9d-d7d3-453e-8849-89887bef2996",
  "toolUseResult": {
    "stdout": "exp_32b_c4_6class: 0v1=0.9923, 1v2=0.6945\n  All AUC: {'0v1': 0.9923, '1v2': 0.6945, '2v3': 0.5978, '3v4': 0.5669, '4v5': 0.5426}\n\nexp_deberta_c4_1b5: 0v1=0.9923, 1v2=0.7052\n  All AUC: {'0v1': 0.9923, '1v2': 0.7052, '2v3': 0.5988, '3v4': 0.5698, '4v5': 0.5475}\n\nexp_deberta_c4_1b5_qwen_cont: 0v1=0.9955, 1v2=0.7194\n  All AUC: {'0v1': 0.9955, '1v2': 0.7194, '2v3': 0.5954, '3v4': 0.5689, '4v5': 0.5502}\n\nmvp_pilot_sat_v1: 0v1=0.9956, 1v2=0.6957\n  All AUC: {'0v1': 0.9956, '1v2': 0.6957, '2v3': 0.5893, '3v4': 0.5434, '4v5': 0.5343}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "d48caeda-225f-4ff9-b89d-9812631ab74c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 41 · 2026-05-23T11:03:30.517Z_

<details><summary>Logged reasoning block</summary>

```text
Found it! `mvp_pilot_sat_v1` is the Qwen-rw experiment. Let me verify:
- Paper: 0v1=.9956, 1v2=.6955, 2v3=.5893, 3v4=.5435, 4v5=.5340
- Registry: 0v1=0.9956, 1v2=0.6957, 2v3=0.5893, 3v4=0.5434, 4v5=0.5343

Discrepancies:
- 1v2: paper .6955, registry 0.6957 ❌


- 3v4: paper .5435, registry 0.5434 ❌
- 4v5: paper .5340, registry 0.5343 ❌

I need to pull the full details for this experiment and also check exp_007_bootstrap_ci for the confidence interval data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "32cfba9d-d7d3-453e-8849-89887bef2996",
  "isSidechain": false,
  "requestId": "req_011CbKPVtfvs3n2zbQj9YbSS",
  "type": "assistant",
  "uuid": "ca53aa71-6676-44de-a4ce-30cb34ac2cdb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RuHVJJy4JrQmd5rZ6pK5B2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 909,
      "cache_read_input_tokens": 58390,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 909,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 58390,
          "cache_creation_input_tokens": 909,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 909
          },
          "type": "message"
        }
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

_source line 42 · 2026-05-23T11:03:33.125Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01NDzWEsiFZ5fSo1cQnHLopF`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get full details of mvp_pilot_sat_v1 and exp_007_bootstrap_ci\nfor eid in ['mvp_pilot_sat_v1', 'exp_007_bootstrap_ci', 'exp_bootstrap_10k']:\n    if eid in exps:\n        exp = exps[eid]\n        metrics = exp.get('metrics', {})\n        print(f'=== {eid} ===')\n        print(json.dumps(metrics, indent=2)[:3000])\n        print()\n\" 2>&1\n",
  "description": "Get Qwen-rw and bootstrap CI details"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ca53aa71-6676-44de-a4ce-30cb34ac2cdb",
  "isSidechain": false,
  "requestId": "req_011CbKPVtfvs3n2zbQj9YbSS",
  "type": "assistant",
  "uuid": "9a745a63-f02e-489f-a4eb-5efb99e014be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RuHVJJy4JrQmd5rZ6pK5B2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 909,
      "cache_read_input_tokens": 58390,
      "output_tokens": 609,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 909,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 609,
          "cache_read_input_tokens": 58390,
          "cache_creation_input_tokens": 909,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 909
          },
          "type": "message"
        }
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

_source line 43 · 2026-05-23T11:03:33.212Z_

<details><summary>↩ Tool result · `toolu_01NDzWEsiFZ5fSo1cQnHLopF`</summary>

```text
=== mvp_pilot_sat_v1 ===
{
  "pairwise_auc": {
    "0v1": 0.9956,
    "1v2": 0.6957,
    "2v3": 0.5893,
    "3v4": 0.5434,
    "4v5": 0.5343
  },
  "pairwise_auc_std": {
    "0v1": 0.0005,
    "1v2": 0.0072,
    "2v3": 0.012,
    "3v4": 0.0053,
    "4v5": 0.0091
  },
  "pairwise_jsd": {
    "0v1": 0.2669,
    "1v2": 0.0163,
    "2v3": 0.0069,
    "3v4": 0.0047,
    "4v5": 0.0041
  },
  "k_star": 2,
  "ordinal_mae": 1.0163,
  "ordinal_accuracy": 0.4182
}

=== exp_007_bootstrap_ci ===
{
  "qwen_rewrite": {
    "0v1": {
      "auc": 0.9956,
      "ci_lower": 0.9946,
      "ci_upper": 0.9965,
      "perm_p": 0.002
    },
    "1v2": {
      "auc": 0.6955,
      "ci_lower": 0.6859,
      "ci_upper": 0.7041,
      "perm_p": 0.002
    },
    "2v3": {
      "auc": 0.5893,
      "ci_lower": 0.5795,
      "ci_upper": 0.5991,
      "perm_p": 0.002
    },
    "3v4": {
      "auc": 0.5435,
      "ci_lower": 0.5333,
      "ci_upper": 0.5551,
      "perm_p": 0.002
    },
    "4v5": {
      "auc": 0.534,
      "ci_lower": 0.5238,
      "ci_upper": 0.5448,
      "perm_p": 0.002
    }
  },
  "pythia_cont": {
    "0v1": {
      "auc": 0.9932,
      "ci_lower": 0.9921,
      "ci_upper": 0.9943,
      "perm_p": 0.002
    },
    "1v2": {
      "auc": 0.6539,
      "ci_lower": 0.6454,
      "ci_upper": 0.663,
      "perm_p": 0.002
    },
    "2v3": {
      "auc": 0.5514,
      "ci_lower": 0.5417,
      "ci_upper": 0.5628,
      "perm_p": 0.002
    },
    "3v4": {
      "auc": 0.5152,
      "ci_lower": 0.5041,
      "ci_upper": 0.526,
      "perm_p": 0.006
    },
    "4v5": {
      "auc": 0.5136,
      "ci_lower": 0.5021,
      "ci_upper": 0.5249,
      "perm_p": 0.008
    }
  },
  "olmo_cont": {
    "0v1": {
      "auc": 0.997,
      "ci_lower": 0.9964,
      "ci_upper": 0.9975,
      "perm_p": 0.002
    },
    "1v2": {
      "auc": 0.6145,
      "ci_lower": 0.6045,
      "ci_upper": 0.6247,
      "perm_p": 0.002
    },
    "2v3": {
      "auc": 0.5496,
      "ci_lower": 0.5399,
      "ci_upper": 0.5596,
      "perm_p": 0.002
    },
    "3v4": {
      "auc": 0.5091,
      "ci_lower": 0.4973,
      "ci_upper": 0.52,
      "perm_p": 0.064
    },
    "4v5": {
      "auc": 0.5045,
      "ci_lower": 0.4932,
      "ci_upper": 0.515,
      "perm_p": 0.232
    }
  },
  "qwen_cont": {
    "0v1": {
      "auc": 0.9971,
      "ci_lower": 0.9963,
      "ci_upper": 0.9978,
      "perm_p": 0.002
    },
    "1v2": {
      "auc": 0.6112,
      "ci_lower": 0.6015,
      "ci_upper": 0.6213,
      "perm_p": 0.002
    },
    "2v3": {
      "auc": 0.5609,
      "ci_lower": 0.5511,
      "ci_upper": 0.5712,
      "perm_p": 0.002
    },
    "3v4": {
      "auc": 0.5409,
      "ci_lower": 0.5308,
      "ci_upper": 0.5508,
      "perm_p": 0.002
    },
    "4v5": {
      "auc": 0.5141,
      "ci_lower": 0.5035,
      "ci_upper": 0.5255,
      "perm_p": 0.006
    }
  },
  "k_star_robust": true,
  "all_1v2_ci_lower_above_060": true,
  "most_marginal": "Qwen-cont CI lower=0.6015, only 0.0015 above threshold"
}

=== exp_bootstrap_10k ===
{
  "configs_tested": 4,
  "configs_missing": 2,
  "results": {
    "llama8b": {
      "auc": 0.6075,
      "ci_1k": [
        0.597,
        0.617
      ],
      "ci_10k": [
        0.598,
        0.617
      ],
      "verdict_1k": "BORDERLINE",
      "verdict_10k": "BORDERLINE",
      "flipped": false
    },
    "gemma2b": {
      "auc": 0.5981,
      "ci_1k": [
        0.588,
        0.608
      ],
      "ci_10k": [
        0.588,
        0.608
      ],
      "verdict_1k": "BORDERLINE",
      "verdict_10k": "BORDERLINE",
      "flipped": false
    },
    "mistral7b": {
      "auc": 0.5902,
      "ci_1k": [
        0.58,
        0.6
      ],
      "ci_10k": [
        0.58,
        0.6
      ],
      "verdict_1k": "K*=1",
      "verdict_10k": "BORDERLINE",
      "flipped_technical": true,
      "note": "CI upper 0.6000\u21920.6001 (noise, +0.01pp). Point estimate 0.5902 << theta. K*=1 unchanged."
    },
    "512tok": {
      "auc": 0.6136,
      "ci_1k": [
        0.604,
        0.623
      ],
      "ci_10k": [
        0.604,
        0.623
      ],
      "verdict_1k": "K*=2",
      "verdict_10k": "K*=2",
      "flipped": false
    }
  },
  "missing": [
    "exp_017_qwen_cont (features.csv not on disk)",
    "exp_002_olmo (features.csv not on disk)"
  ],
  "conclusion": "No substantive K* flips. 10K CI ~3% tighter. 1K resamples confirmed robust."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9a745a63-f02e-489f-a4eb-5efb99e014be",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "791c9db4-4706-41df-a171-e9da0382d7e5",
  "toolUseResult": {
    "stdout": "=== mvp_pilot_sat_v1 ===\n{\n  \"pairwise_auc\": {\n    \"0v1\": 0.9956,\n    \"1v2\": 0.6957,\n    \"2v3\": 0.5893,\n    \"3v4\": 0.5434,\n    \"4v5\": 0.5343\n  },\n  \"pairwise_auc_std\": {\n    \"0v1\": 0.0005,\n    \"1v2\": 0.0072,\n    \"2v3\": 0.012,\n    \"3v4\": 0.0053,\n    \"4v5\": 0.0091\n  },\n  \"pairwise_jsd\": {\n    \"0v1\": 0.2669,\n    \"1v2\": 0.0163,\n    \"2v3\": 0.0069,\n    \"3v4\": 0.0047,\n    \"4v5\": 0.0041\n  },\n  \"k_star\": 2,\n  \"ordinal_mae\": 1.0163,\n  \"ordinal_accuracy\": 0.4182\n}\n\n=== exp_007_bootstrap_ci ===\n{\n  \"qwen_rewrite\": {\n    \"0v1\": {\n      \"auc\": 0.9956,\n      \"ci_lower\": 0.9946,\n      \"ci_upper\": 0.9965,\n      \"perm_p\": 0.002\n    },\n    \"1v2\": {\n      \"auc\": 0.6955,\n      \"ci_lower\": 0.6859,\n      \"ci_upper\": 0.7041,\n      \"perm_p\": 0.002\n    },\n    \"2v3\": {\n      \"auc\": 0.5893,\n      \"ci_lower\": 0.5795,\n      \"ci_upper\": 0.5991,\n      \"perm_p\": 0.002\n    },\n    \"3v4\": {\n      \"auc\": 0.5435,\n      \"ci_lower\": 0.5333,\n      \"ci_upper\": 0.5551,\n      \"perm_p\": 0.002\n    },\n    \"4v5\": {\n      \"auc\": 0.534,\n      \"ci_lower\": 0.5238,\n      \"ci_upper\": 0.5448,\n      \"perm_p\": 0.002\n    }\n  },\n  \"pythia_cont\": {\n    \"0v1\": {\n      \"auc\": 0.9932,\n      \"ci_lower\": 0.9921,\n      \"ci_upper\": 0.9943,\n      \"perm_p\": 0.002\n    },\n    \"1v2\": {\n      \"auc\": 0.6539,\n      \"ci_lower\": 0.6454,\n      \"ci_upper\": 0.663,\n      \"perm_p\": 0.002\n    },\n    \"2v3\": {\n      \"auc\": 0.5514,\n      \"ci_lower\": 0.5417,\n      \"ci_upper\": 0.5628,\n      \"perm_p\": 0.002\n    },\n    \"3v4\": {\n      \"auc\": 0.5152,\n      \"ci_lower\": 0.5041,\n      \"ci_upper\": 0.526,\n      \"perm_p\": 0.006\n    },\n    \"4v5\": {\n      \"auc\": 0.5136,\n      \"ci_lower\": 0.5021,\n      \"ci_upper\": 0.5249,\n      \"perm_p\": 0.008\n    }\n  },\n  \"olmo_cont\": {\n    \"0v1\": {\n      \"auc\": 0.997,\n      \"ci_lower\": 0.9964,\n      \"ci_upper\": 0.9975,\n      \"perm_p\": 0.002\n    },\n    \"1v2\": {\n      \"auc\": 0.6145,\n      \"ci_lower\": 0.6045,\n      \"ci_upper\": 0.6247,\n      \"perm_p\": 0.002\n    },\n    \"2v3\": {\n      \"auc\": 0.5496,\n      \"ci_lower\": 0.5399,\n      \"ci_upper\": 0.5596,\n      \"perm_p\": 0.002\n    },\n    \"3v4\": {\n      \"auc\": 0.5091,\n      \"ci_lower\": 0.4973,\n      \"ci_upper\": 0.52,\n      \"perm_p\": 0.064\n    },\n    \"4v5\": {\n      \"auc\": 0.5045,\n      \"ci_lower\": 0.4932,\n      \"ci_upper\": 0.515,\n      \"perm_p\": 0.232\n    }\n  },\n  \"qwen_cont\": {\n    \"0v1\": {\n      \"auc\": 0.9971,\n      \"ci_lower\": 0.9963,\n      \"ci_upper\": 0.9978,\n      \"perm_p\": 0.002\n    },\n    \"1v2\": {\n      \"auc\": 0.6112,\n      \"ci_lower\": 0.6015,\n      \"ci_upper\": 0.6213,\n      \"perm_p\": 0.002\n    },\n    \"2v3\": {\n      \"auc\": 0.5609,\n      \"ci_lower\": 0.5511,\n      \"ci_upper\": 0.5712,\n      \"perm_p\": 0.002\n    },\n    \"3v4\": {\n      \"auc\": 0.5409,\n      \"ci_lower\": 0.5308,\n      \"ci_upper\": 0.5508,\n      \"perm_p\": 0.002\n    },\n    \"4v5\": {\n      \"auc\": 0.5141,\n      \"ci_lower\": 0.5035,\n      \"ci_upper\": 0.5255,\n      \"perm_p\": 0.006\n    }\n  },\n  \"k_star_robust\": true,\n  \"all_1v2_ci_lower_above_060\": true,\n  \"most_marginal\": \"Qwen-cont CI lower=0.6015, only 0.0015 above threshold\"\n}\n\n=== exp_bootstrap_10k ===\n{\n  \"configs_tested\": 4,\n  \"configs_missing\": 2,\n  \"results\": {\n    \"llama8b\": {\n      \"auc\": 0.6075,\n      \"ci_1k\": [\n        0.597,\n        0.617\n      ],\n      \"ci_10k\": [\n        0.598,\n        0.617\n      ],\n      \"verdict_1k\": \"BORDERLINE\",\n      \"verdict_10k\": \"BORDERLINE\",\n      \"flipped\": false\n    },\n    \"gemma2b\": {\n      \"auc\": 0.5981,\n      \"ci_1k\": [\n        0.588,\n        0.608\n      ],\n      \"ci_10k\": [\n        0.588,\n        0.608\n      ],\n      \"verdict_1k\": \"BORDERLINE\",\n      \"verdict_10k\": \"BORDERLINE\",\n      \"flipped\": false\n    },\n    \"mistral7b\": {\n      \"auc\": 0.5902,\n      \"ci_1k\": [\n        0.58,\n        0.6\n      ],\n      \"ci_10k\": [\n        0.58,\n        0.6\n      ],\n      \"verdict_1k\": \"K*=1\",\n      \"verdict_10k\": \"BORDERLINE\",\n      \"flipped_technical\": true,\n      \"note\": \"CI upper 0.6000\\u21920.6001 (noise, +0.01pp). Point estimate 0.5902 << theta. K*=1 unchanged.\"\n    },\n    \"512tok\": {\n      \"auc\": 0.6136,\n      \"ci_1k\": [\n        0.604,\n        0.623\n      ],\n      \"ci_10k\": [\n        0.604,\n        0.623\n      ],\n      \"verdict_1k\": \"K*=2\",\n      \"verdict_10k\": \"K*=2\",\n      \"flipped\": false\n    }\n  },\n  \"missing\": [\n    \"exp_017_qwen_cont (features.csv not on disk)\",\n    \"exp_002_olmo (features.csv not on disk)\"\n  ],\n  \"conclusion\": \"No substantive K* flips. 10K CI ~3% tighter. 1K resamples confirmed robust.\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "9a745a63-f02e-489f-a4eb-5efb99e014be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 44 · 2026-05-23T11:04:12.223Z_

<details><summary>Logged reasoning block</summary>

```text
Now I'm getting a clearer picture. Let me identify the canonical experiments:

**Table 2 (and Table 10 overlap):**

1. **Qwen-rw**: exp_007_bootstrap_ci.qwen_rewrite → 0v1=0.9956, 1v2=0.6955, 2v3=0.5893, 3v4=0.5435, 4v5=0.534
   - But mvp_pilot_sat_v1 → 0v1=0.9956, 1v2=0.6957, 2v3=0.5893, 3v4=0.5434, 4v5=0.5343
   - The exp_007 values match the paper perfectly, so that's the bootstrap re-evaluation while mvp_pilot was the original run.

2. **Pythia**: exp_001_pythia_depth shows 0v1=0.9722, 1v2=0.6074, 2v3=0.544, 3v4=0.5051, 4v5=0.5079, though exp_007.pythia_cont only has the first comparison at 0v1=0.9932.
   - The exp_007 Pythia numbers don't match the paper at all—that 0.9932 is clearly from a different scorer, so exp_001 is the actual canonical Pythia experiment.

3. **OLMo**: The paper reports 0v1=.9860, 1v2=.5001, 2v3=.4973, 3v4=.5024, 4v5=.4942, and exp_002_olmo_depth is tracking almost perfectly with 0v1=0.9861, 1v2=0.5001, 2v3=0.4972.

Now looking at the exp_olmo1b_c4_rerun numbers—the 0v1 value of 0.986 matches the paper's .9860 when rounded, but the 1v2 is 0.508 instead of .5001, which is off. Meanwhile exp_002 nails the 1v2 value exactly, so it seems like the paper might be pulling from different experiments for different metrics. Looking at the pattern more carefully, it seems the paper values align with the rerun results for most comparisons (2v3 through 4v5), but 0v1 and 1v2 show different matches—0v1 could round from the rerun value while 1v2 matches exp_002 exactly, suggesting the paper might be pulling from mixed sources rather than a single consistent experiment. So exp_007 used a different scorer entirely — Qwen rather than self-scored — which explains why those OLMo values are completely off. The only exp_007 values matching the paper are for models where Qwen is the self-scorer. I need to find where the paper's OLMo bootstrap CIs actually come from, since they don't match exp_002 or exp_olmo1b_c4_rerun either. Let me search through other experiments to see if there's another OLMo run with those exact AUC values.

Wait, I should reconsider the paper's methodology more carefully. The description mentions all features come from an external scorer model, so maybe the paper actually uses Qwen as the universal scorer across all models, not self-scoring. Let me check what scorer exp_002 actually used.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "791c9db4-4706-41df-a171-e9da0382d7e5",
  "isSidechain": false,
  "requestId": "req_011CbKPWyygpGsSwSYctdNqc",
  "type": "assistant",
  "uuid": "a3e6ba60-f0b9-41d2-bf6a-14c10143337a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QhzhyWwg6kpXK9G7jqZYdf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2836,
      "cache_read_input_tokens": 59299,
      "output_tokens": 2249,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2836,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2249,
          "cache_read_input_tokens": 59299,
          "cache_creation_input_tokens": 2836,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2836
          },
          "type": "message"
        }
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

_source line 45 · 2026-05-23T11:04:22.237Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01Y2JpgyR1mSke1XphvDQCZG`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get scorer info and full metrics for OLMo and Pythia experiments\nfor eid in ['exp_002_olmo_depth', 'exp_001_pythia_depth', 'exp_olmo1b_c4_rerun', 'exp_olmo1b_10k', 'exp_pythia14b_c4_rerun', 'exp_pythia14b_c4_10k', 'exp_019_mistral7b_depth', 'exp_pythia69b_c4_nuc']:\n    if eid in exps:\n        exp = exps[eid]\n        metrics = exp.get('metrics', {})\n        print(f'=== {eid} ===')\n        # Print scorer info\n        for k in ['scorer', 'note', 'NOTE']:\n            if k in metrics:\n                print(f'  {k}: {metrics[k]}')\n        # Print all AUC and CI\n        for k, v in sorted(metrics.items()):\n            if 'auc' in k.lower() or 'ci' in k.lower() or 'AUC' in k or 'boot' in k.lower():\n                print(f'  {k}: {v}')\n        print()\n\" 2>&1\n",
  "description": "Get scorer info for OLMo and Pythia"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a3e6ba60-f0b9-41d2-bf6a-14c10143337a",
  "isSidechain": false,
  "requestId": "req_011CbKPWyygpGsSwSYctdNqc",
  "type": "assistant",
  "uuid": "ccd4e14c-ff07-4275-a3bc-589dedde12ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QhzhyWwg6kpXK9G7jqZYdf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2836,
      "cache_read_input_tokens": 59299,
      "output_tokens": 2249,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2836,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2249,
          "cache_read_input_tokens": 59299,
          "cache_creation_input_tokens": 2836,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2836
          },
          "type": "message"
        }
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

_source line 46 · 2026-05-23T11:04:22.333Z_

<details><summary>↩ Tool result · `toolu_01Y2JpgyR1mSke1XphvDQCZG`</summary>

```text
=== exp_002_olmo_depth ===
  scorer: Qwen2.5-1.5B-Instruct
  note: Updated to Qwen cross-scoring (D107). Self-scored 1v2=0.6145 K*=2, Qwen-scored 1v2=0.5001 K*=1.
  pairwise_auc: {'0v1': 0.9861, '1v2': 0.5001, '2v3': 0.4972, '3v4': 0.5034, '4v5': 0.4971}

=== exp_001_pythia_depth ===
  scorer: Qwen2.5-1.5B-Instruct
  note: Updated to Qwen cross-scoring (D107). Self-scored 1v2=0.6539, Qwen-scored 1v2=0.6074.
  bootstrap_ci: {'1v2': {'auc_oof': 0.6072, 'boot_mean': 0.6073, 'boot_std': 0.005, 'ci_95': [0.5975, 0.6172], 'ci_995_bonferroni': [0.5934, 0.621], 'perm_p': 0.0001, 'bonferroni_pass': False}}
  pairwise_auc: {'0v1': 0.9722, '1v2': 0.6074, '2v3': 0.544, '3v4': 0.5051, '4v5': 0.5079}
  pairwise_auc_std: {'0v1': 0.0039, '1v2': 0.0078, '2v3': 0.0067, '3v4': 0.0032, '4v5': 0.0101}

=== exp_olmo1b_c4_rerun ===
  0v1_auc: 0.986
  1v2_auc: 0.508
  2v3_auc: 0.4973
  3v4_auc: 0.5024
  4v5_auc: 0.4942

=== exp_olmo1b_10k ===
  pairwise_auc: {'0v1': 0.9871, '1v2': 0.4984, '2v3': 0.5059, '3v4': 0.5061, '4v5': 0.5074}

=== exp_pythia14b_c4_rerun ===
  NOTE: GREEDY decoding -- inflated AUC, not comparable to main table
  0v1_auc: 0.9979
  1v2_auc: 0.8786
  2v3_auc: 0.5399
  3v4_auc: 0.5062
  4v5_auc: 0.5025

=== exp_pythia14b_c4_10k ===
  AUC_0v1: 0.9712
  AUC_1v2: 0.6175
  AUC_2v3: 0.5364
  AUC_3v4: 0.5134
  AUC_4v5: 0.5088
  bootstrap_1v2_95CI: [0.6108, 0.6242]
  bootstrap_1v2_995CI_bonferroni: [0.6078, 0.6273]

=== exp_019_mistral7b_depth ===
  bootstrap_ci_1v2: {'ci_lower': 0.5835, 'ci_upper': 0.6032, 'p_auc_leq_060': 0.9017}
  pairwise_auc: {'0v1': 0.9843, '1v2': 0.5935, '2v3': 0.5402, '3v4': 0.5232, '4v5': 0.5181}

=== exp_pythia69b_c4_nuc ===
  scorer: Qwen-1.5B
  note: 1v2 AUC borderline (0.0045 below threshold)
  pairwise_auc: {'0v1': 0.9599, '1v2': 0.5955, '2v3': 0.5298, '3v4': 0.5135}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ccd4e14c-ff07-4275-a3bc-589dedde12ed",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "060a06dd-a336-495c-b103-a67baad7016c",
  "toolUseResult": {
    "stdout": "=== exp_002_olmo_depth ===\n  scorer: Qwen2.5-1.5B-Instruct\n  note: Updated to Qwen cross-scoring (D107). Self-scored 1v2=0.6145 K*=2, Qwen-scored 1v2=0.5001 K*=1.\n  pairwise_auc: {'0v1': 0.9861, '1v2': 0.5001, '2v3': 0.4972, '3v4': 0.5034, '4v5': 0.4971}\n\n=== exp_001_pythia_depth ===\n  scorer: Qwen2.5-1.5B-Instruct\n  note: Updated to Qwen cross-scoring (D107). Self-scored 1v2=0.6539, Qwen-scored 1v2=0.6074.\n  bootstrap_ci: {'1v2': {'auc_oof': 0.6072, 'boot_mean': 0.6073, 'boot_std': 0.005, 'ci_95': [0.5975, 0.6172], 'ci_995_bonferroni': [0.5934, 0.621], 'perm_p': 0.0001, 'bonferroni_pass': False}}\n  pairwise_auc: {'0v1': 0.9722, '1v2': 0.6074, '2v3': 0.544, '3v4': 0.5051, '4v5': 0.5079}\n  pairwise_auc_std: {'0v1': 0.0039, '1v2': 0.0078, '2v3': 0.0067, '3v4': 0.0032, '4v5': 0.0101}\n\n=== exp_olmo1b_c4_rerun ===\n  0v1_auc: 0.986\n  1v2_auc: 0.508\n  2v3_auc: 0.4973\n  3v4_auc: 0.5024\n  4v5_auc: 0.4942\n\n=== exp_olmo1b_10k ===\n  pairwise_auc: {'0v1': 0.9871, '1v2': 0.4984, '2v3': 0.5059, '3v4': 0.5061, '4v5': 0.5074}\n\n=== exp_pythia14b_c4_rerun ===\n  NOTE: GREEDY decoding -- inflated AUC, not comparable to main table\n  0v1_auc: 0.9979\n  1v2_auc: 0.8786\n  2v3_auc: 0.5399\n  3v4_auc: 0.5062\n  4v5_auc: 0.5025\n\n=== exp_pythia14b_c4_10k ===\n  AUC_0v1: 0.9712\n  AUC_1v2: 0.6175\n  AUC_2v3: 0.5364\n  AUC_3v4: 0.5134\n  AUC_4v5: 0.5088\n  bootstrap_1v2_95CI: [0.6108, 0.6242]\n  bootstrap_1v2_995CI_bonferroni: [0.6078, 0.6273]\n\n=== exp_019_mistral7b_depth ===\n  bootstrap_ci_1v2: {'ci_lower': 0.5835, 'ci_upper': 0.6032, 'p_auc_leq_060': 0.9017}\n  pairwise_auc: {'0v1': 0.9843, '1v2': 0.5935, '2v3': 0.5402, '3v4': 0.5232, '4v5': 0.5181}\n\n=== exp_pythia69b_c4_nuc ===\n  scorer: Qwen-1.5B\n  note: 1v2 AUC borderline (0.0045 below threshold)\n  pairwise_auc: {'0v1': 0.9599, '1v2': 0.5955, '2v3': 0.5298, '3v4': 0.5135}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "ccd4e14c-ff07-4275-a3bc-589dedde12ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 47_

```json
{
  "type": "last-prompt",
  "leafUuid": "060a06dd-a336-495c-b103-a67baad7016c",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 48_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 49 · 2026-05-23T11:05:19.628Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a much clearer picture. Let me now get the bootstrap CI data for the experiments that need it. Let me also check exp_007 more carefully for the CIs used in Table 2.

For Table 2, the CIs are:
- Qwen-rw 1v2: [.686,.704] → exp_007: [0.6859, 0.7041] → rounds to [.686, .704] ✓
- Qwen-rw 2v3: [.580,.599] → exp_007: [0.5795, 0.5991] → rounds to [.580, .599] ✓


- Pythia 1v2: [.598,.617] → exp_001: [0.5975, 0.6172] → rounds to [.598, .617] ✓

Now I need to track down the remaining CIs for Pythia 2v3, OLMo 1v2, OLMo 2v3, and finish verifying Qwen-cont 1v2 which appears to be cut off. Now I'm tracking down the bootstrap confidence intervals for the remaining models—Python, OLMo, and Mistral—by checking the relevant experiment files. I'm noticing some small discrepancies between what the paper reports and what I'm finding in the raw data, like the Qwen-rw values differing slightly between experiments, so I need to verify which source the paper actually used for each model's final numbers. _002. So it looks like the paper might be pulling from a mix of sources—the rerun for some comparisons and exp_002 for others, or possibly there's a third dataset I haven't identified yet.

Rather than chase down every possible version, I should document these discrepancies clearly and move forward with the audit. I also need to pull the confidence intervals for Mistral, Pythia-6.9B, and Gemma from Table 10, then locate the corresponding experiments for the new model configs: Qwen-base from exp_016, LLaMA-8B from exp_018, and Mistral-7B from exp_019.

Looking at the Mistral-7B values in the paper versus what's in exp_019, there's a major mismatch — the paper shows 0v1=.9170 but the registry has 0v1=0.9843. Something's off with how I'm reading the table, so let me go back and parse Table 10 more carefully. I'm noticing a major discrepancy with Mistral-7B's score—the table shows .9170 for 0v1, but the registry lists 0.9843, which is a significant difference. Let me reread the LaTeX formatting more carefully to make sure I'm parsing the columns correctly. Looking at the 0v1 row values, most models show strong AUC scores ranging from .9170 to .9971, with confidence intervals provided for some of the larger models like Qwen-7B, Qwen-base, LLaMA-8B, and Mistral-7B, while the smaller or earlier configs are missing CI data.

Now I'm noticing a discrepancy between what the paper reports for Mistral 0v1 and what experiment 019 shows, so I'm carefully re-examining the appendix line to verify the exact values character by character. I'm noticing a massive gap between what the paper shows for Mistral-7B 0v1 (0.917) and what exp_019_mistral7b_depth reports (0.9843), so I need to figure out which experiment actually corresponds to the paper's results. It's possible exp_019 was re-run with different scoring, or maybe there's another Mistral experiment I should be looking at instead. Looking for the Mistral cross-scorer experiment variant that might explain the .917 discrepancy.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "060a06dd-a336-495c-b103-a67baad7016c",
  "isSidechain": false,
  "requestId": "req_011CbKPabyyGrb3Ycj9k4shD",
  "type": "assistant",
  "uuid": "ff3d1b26-4b3d-4713-9ae3-1eddca6fe00b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0146no9Fxkoj8oqDLEb28STy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3369,
      "cache_read_input_tokens": 62135,
      "output_tokens": 4011,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3369,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4011,
          "cache_read_input_tokens": 62135,
          "cache_creation_input_tokens": 3369,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3369
          },
          "type": "message"
        }
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

_source line 50 · 2026-05-23T11:05:28.582Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01CK4yXNCpYtcBhguXpLkk7c`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get Mistral-related and other experiments\nfor eid in ['exp_019b_mistral_cross_scorer', 'exp_019_mistral7b_depth']:\n    if eid in exps:\n        exp = exps[eid]\n        metrics = exp.get('metrics', {})\n        print(f'=== {eid} ===')\n        print(json.dumps(metrics, indent=2)[:2000])\n        print()\n\n# Also search for any experiment with 0v1 near 0.917\nprint('=== Searching for 0v1 near 0.917 ===')\nfor eid, exp in sorted(exps.items()):\n    metrics = exp.get('metrics', {})\n    pauc = metrics.get('pairwise_auc', {})\n    if isinstance(pauc, dict):\n        v01 = pauc.get('0v1', None)\n        if v01 and isinstance(v01, (int, float)) and 0.915 < v01 < 0.920:\n            print(f'{eid}: 0v1={v01}, full={pauc}')\n\" 2>&1\n",
  "description": "Get Mistral cross-scorer and search 0v1≈0.917"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ff3d1b26-4b3d-4713-9ae3-1eddca6fe00b",
  "isSidechain": false,
  "requestId": "req_011CbKPabyyGrb3Ycj9k4shD",
  "type": "assistant",
  "uuid": "f3d42874-844e-46e3-b67f-dde64eaf4796",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0146no9Fxkoj8oqDLEb28STy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3369,
      "cache_read_input_tokens": 62135,
      "output_tokens": 4011,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3369,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4011,
          "cache_read_input_tokens": 62135,
          "cache_creation_input_tokens": 3369,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3369
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-23T11:05:28.669Z_

<details><summary>↩ Tool result · `toolu_01CK4yXNCpYtcBhguXpLkk7c`</summary>

```text
=== exp_019b_mistral_cross_scorer ===
{
  "k_star": 1,
  "pairwise_auc": {
    "0v1": 0.9209,
    "1v2": 0.5695,
    "2v3": 0.5335,
    "3v4": 0.514,
    "4v5": 0.5184
  },
  "bootstrap_ci": {
    "0v1": {
      "mean": 0.9209,
      "ci_lower": 0.9189,
      "ci_upper": 0.9229,
      "pass_060": true
    },
    "1v2": {
      "mean": 0.5696,
      "ci_lower": 0.5645,
      "ci_upper": 0.5746,
      "pass_060": false
    },
    "2v3": {
      "mean": 0.5335,
      "ci_lower": 0.5283,
      "ci_upper": 0.5382,
      "pass_060": false
    },
    "3v4": {
      "mean": 0.514,
      "ci_lower": 0.5063,
      "ci_upper": 0.5213,
      "pass_060": false
    },
    "4v5": {
      "mean": 0.5183,
      "ci_lower": 0.5128,
      "ci_upper": 0.5244,
      "pass_060": false
    }
  },
  "jsd": {
    "0v1": 0.08355,
    "1v2": 0.007642,
    "2v3": 0.004752,
    "3v4": 0.004255,
    "4v5": 0.003758
  },
  "ordinal_mae": 1.3737,
  "ordinal_accuracy": 0.3179,
  "top3_features": [
    "freq_entropy",
    "surp_d1_skew",
    "surp_d1_mean"
  ],
  "key_finding": "Cross-scorer (Qwen-1.5B scoring Mistral text) confirms K*=1. 1v2 AUC=0.5695 (self-scorer was 0.5935) \u2014 cross-scorer LOWER, not higher. Mistral K*=1 is genuine (inherent to Mistral generations), NOT a self-scorer artifact."
}

=== exp_019_mistral7b_depth ===
{
  "k_star": 1,
  "pairwise_auc": {
    "0v1": 0.9843,
    "1v2": 0.5935,
    "2v3": 0.5402,
    "3v4": 0.5232,
    "4v5": 0.5181
  },
  "bootstrap_ci_1v2": {
    "ci_lower": 0.5835,
    "ci_upper": 0.6032,
    "p_auc_leq_060": 0.9017
  },
  "jsd": {
    "0v1": 0.124194,
    "1v2": 0.008051,
    "2v3": 0.005047,
    "3v4": 0.004516,
    "4v5": 0.004109
  },
  "ordinal_mae": 1.2275,
  "ordinal_accuracy": 0.3567,
  "top3_features": [
    "freq_entropy",
    "surp_d1_skew",
    "surp_d1_mean"
  ]
}

=== Searching for 0v1 near 0.917 ===
exp_code_llama8b: 0v1=0.9161, full={'0v1': 0.9161, '1v2': 0.7394, '2v3': 0.5112, '3v4': 0.52, '4v5': 0.4996}
exp_code_mistral7b: 0v1=0.9191, full={'0v1': 0.9191, '1v2': 0.6152, '2v3': 0.5293, '3v4': 0.5286, '4v5': 0.5099}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f3d42874-844e-46e3-b67f-dde64eaf4796",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "79210440-4207-45c8-8888-b7f48cf0b5da",
  "toolUseResult": {
    "stdout": "=== exp_019b_mistral_cross_scorer ===\n{\n  \"k_star\": 1,\n  \"pairwise_auc\": {\n    \"0v1\": 0.9209,\n    \"1v2\": 0.5695,\n    \"2v3\": 0.5335,\n    \"3v4\": 0.514,\n    \"4v5\": 0.5184\n  },\n  \"bootstrap_ci\": {\n    \"0v1\": {\n      \"mean\": 0.9209,\n      \"ci_lower\": 0.9189,\n      \"ci_upper\": 0.9229,\n      \"pass_060\": true\n    },\n    \"1v2\": {\n      \"mean\": 0.5696,\n      \"ci_lower\": 0.5645,\n      \"ci_upper\": 0.5746,\n      \"pass_060\": false\n    },\n    \"2v3\": {\n      \"mean\": 0.5335,\n      \"ci_lower\": 0.5283,\n      \"ci_upper\": 0.5382,\n      \"pass_060\": false\n    },\n    \"3v4\": {\n      \"mean\": 0.514,\n      \"ci_lower\": 0.5063,\n      \"ci_upper\": 0.5213,\n      \"pass_060\": false\n    },\n    \"4v5\": {\n      \"mean\": 0.5183,\n      \"ci_lower\": 0.5128,\n      \"ci_upper\": 0.5244,\n      \"pass_060\": false\n    }\n  },\n  \"jsd\": {\n    \"0v1\": 0.08355,\n    \"1v2\": 0.007642,\n    \"2v3\": 0.004752,\n    \"3v4\": 0.004255,\n    \"4v5\": 0.003758\n  },\n  \"ordinal_mae\": 1.3737,\n  \"ordinal_accuracy\": 0.3179,\n  \"top3_features\": [\n    \"freq_entropy\",\n    \"surp_d1_skew\",\n    \"surp_d1_mean\"\n  ],\n  \"key_finding\": \"Cross-scorer (Qwen-1.5B scoring Mistral text) confirms K*=1. 1v2 AUC=0.5695 (self-scorer was 0.5935) \\u2014 cross-scorer LOWER, not higher. Mistral K*=1 is genuine (inherent to Mistral generations), NOT a self-scorer artifact.\"\n}\n\n=== exp_019_mistral7b_depth ===\n{\n  \"k_star\": 1,\n  \"pairwise_auc\": {\n    \"0v1\": 0.9843,\n    \"1v2\": 0.5935,\n    \"2v3\": 0.5402,\n    \"3v4\": 0.5232,\n    \"4v5\": 0.5181\n  },\n  \"bootstrap_ci_1v2\": {\n    \"ci_lower\": 0.5835,\n    \"ci_upper\": 0.6032,\n    \"p_auc_leq_060\": 0.9017\n  },\n  \"jsd\": {\n    \"0v1\": 0.124194,\n    \"1v2\": 0.008051,\n    \"2v3\": 0.005047,\n    \"3v4\": 0.004516,\n    \"4v5\": 0.004109\n  },\n  \"ordinal_mae\": 1.2275,\n  \"ordinal_accuracy\": 0.3567,\n  \"top3_features\": [\n    \"freq_entropy\",\n    \"surp_d1_skew\",\n    \"surp_d1_mean\"\n  ]\n}\n\n=== Searching for 0v1 near 0.917 ===\nexp_code_llama8b: 0v1=0.9161, full={'0v1': 0.9161, '1v2': 0.7394, '2v3': 0.5112, '3v4': 0.52, '4v5': 0.4996}\nexp_code_mistral7b: 0v1=0.9191, full={'0v1': 0.9191, '1v2': 0.6152, '2v3': 0.5293, '3v4': 0.5286, '4v5': 0.5099}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "f3d42874-844e-46e3-b67f-dde64eaf4796",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 52 · 2026-05-23T11:05:40.261Z_

<details><summary>Logged reasoning block</summary>

```text
Interesting! So exp_019_mistral7b_depth is self-scored (0v1=0.9843) and exp_019b_mistral_cross_scorer is Qwen-scored (0v1=0.9209). Neither matches the paper value of .9170 for Mistral-7B.

Wait — .9170. Let me check if exp_019b_mistral_cross_scorer could be the source. Its 0v1=0.9209 ≠ 0.9170. 

Hmm, and exp_019 self-scored: 0v1=0.9843, 1v2=0.5935, which also doesn't match paper .9170, .5750.
 
Looking at the full paper values for Mistral-7B, none of the registry experiments align with any of them — the cross-scorer's 1v2=0.5695 and self-scorer's 1v2=0.5935 both diverge from the paper's .5750. The Mistral 0v1 value of .917 is suspiciously close to LLaMA-8B's .9224, which makes me wonder if there's some confusion in the paper's reported numbers.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "79210440-4207-45c8-8888-b7f48cf0b5da",
  "isSidechain": false,
  "requestId": "req_011CbKPfVcNwFH5Yt5nT3A4H",
  "type": "assistant",
  "uuid": "833bbcf3-4657-4ad4-b76f-d2c8f3f31d83",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cy6TwucwS8VRgEFk6RrU2D",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5132,
      "cache_read_input_tokens": 65504,
      "output_tokens": 1142,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5132,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1142,
          "cache_read_input_tokens": 65504,
          "cache_creation_input_tokens": 5132,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5132
          },
          "type": "message"
        }
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

_source line 53 · 2026-05-23T11:05:51.161Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01SsySmGGagU8xSjwsKxJ24f`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Search for 1v2 near 0.575 (Mistral paper value)\nprint('=== 1v2 near 0.575 ===')\nfor eid, exp in sorted(exps.items()):\n    metrics = exp.get('metrics', {})\n    pauc = metrics.get('pairwise_auc', {})\n    if isinstance(pauc, dict):\n        v12 = pauc.get('1v2', None)\n        if v12 and isinstance(v12, (int, float)) and 0.570 < v12 < 0.580:\n            v01 = pauc.get('0v1', 'N/A')\n            print(f'{eid}: 0v1={v01}, 1v2={v12}, full={pauc}')\n\n# Search for 0v1 near 0.917 more broadly\nprint()\nprint('=== 0v1 in 0.91-0.92 range ===')\nfor eid, exp in sorted(exps.items()):\n    metrics = exp.get('metrics', {})\n    pauc = metrics.get('pairwise_auc', {})\n    if isinstance(pauc, dict):\n        v01 = pauc.get('0v1', None)\n        if v01 and isinstance(v01, (int, float)) and 0.91 < v01 < 0.92:\n            print(f'{eid}: 0v1={v01}, 1v2={pauc.get(\\\"1v2\\\",\\\"N/A\\\")}')\n\n# Also look at Mistral with _qwen prefix or suffix\nprint()\nprint('=== Mistral experiments ===')\nfor eid, exp in sorted(exps.items()):\n    if 'mistral' in eid.lower():\n        metrics = exp.get('metrics', {})\n        pauc = metrics.get('pairwise_auc', {})\n        print(f'{eid}: AUC={pauc}')\n\" 2>&1\n",
  "description": "Search for Mistral paper values in registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "833bbcf3-4657-4ad4-b76f-d2c8f3f31d83",
  "isSidechain": false,
  "requestId": "req_011CbKPfVcNwFH5Yt5nT3A4H",
  "type": "assistant",
  "uuid": "c7aef4b9-9375-4b2d-b6e5-654f2ced5719",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cy6TwucwS8VRgEFk6RrU2D",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5132,
      "cache_read_input_tokens": 65504,
      "output_tokens": 1142,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5132,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1142,
          "cache_read_input_tokens": 65504,
          "cache_creation_input_tokens": 5132,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5132
          },
          "type": "message"
        }
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

_source line 54 · 2026-05-23T11:05:51.256Z_

<details><summary>↩ Tool result · `toolu_01SsySmGGagU8xSjwsKxJ24f`</summary>

```text
=== 1v2 near 0.575 ===

=== 0v1 in 0.91-0.92 range ===
exp_code_llama8b: 0v1=0.9161, 1v2=0.7394
exp_code_mistral7b: 0v1=0.9191, 1v2=0.6152

=== Mistral experiments ===
exp_019_mistral7b_depth: AUC={'0v1': 0.9843, '1v2': 0.5935, '2v3': 0.5402, '3v4': 0.5232, '4v5': 0.5181}
exp_019b_mistral_cross_scorer: AUC={'0v1': 0.9209, '1v2': 0.5695, '2v3': 0.5335, '3v4': 0.514, '4v5': 0.5184}
exp_arXiv_mistral7b: AUC={'0v1': 0.9848, '1v2': 0.8201, '2v3': 0.6275, '3v4': 0.5295, '4v5': 0.5295}
exp_arXiv_mistral7b_crossscorer: AUC={}
exp_code_mistral7b: AUC={'0v1': 0.9191, '1v2': 0.6152, '2v3': 0.5293, '3v4': 0.5286, '4v5': 0.5099}
exp_wiki_mistral7b: AUC={}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c7aef4b9-9375-4b2d-b6e5-654f2ced5719",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "45feec99-17e4-48b1-b64e-c43d881c0091",
  "toolUseResult": {
    "stdout": "=== 1v2 near 0.575 ===\n\n=== 0v1 in 0.91-0.92 range ===\nexp_code_llama8b: 0v1=0.9161, 1v2=0.7394\nexp_code_mistral7b: 0v1=0.9191, 1v2=0.6152\n\n=== Mistral experiments ===\nexp_019_mistral7b_depth: AUC={'0v1': 0.9843, '1v2': 0.5935, '2v3': 0.5402, '3v4': 0.5232, '4v5': 0.5181}\nexp_019b_mistral_cross_scorer: AUC={'0v1': 0.9209, '1v2': 0.5695, '2v3': 0.5335, '3v4': 0.514, '4v5': 0.5184}\nexp_arXiv_mistral7b: AUC={'0v1': 0.9848, '1v2': 0.8201, '2v3': 0.6275, '3v4': 0.5295, '4v5': 0.5295}\nexp_arXiv_mistral7b_crossscorer: AUC={}\nexp_code_mistral7b: AUC={'0v1': 0.9191, '1v2': 0.6152, '2v3': 0.5293, '3v4': 0.5286, '4v5': 0.5099}\nexp_wiki_mistral7b: AUC={}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "c7aef4b9-9375-4b2d-b6e5-654f2ced5719",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 55 · 2026-05-23T11:06:36.970Z_

<details><summary>Logged reasoning block</summary>

```text
Neither Mistral experiment matches the paper's values for Mistral-7B (0v1=.9170, 1v2=.5750, 2v3=.5369, 3v4=.5174, 4v5=.5175).

The closest is exp_019b_mistral_cross_scorer with 0v1=0.9209 (paper .9170), but 1v2=0.5695 (paper .5750), 2v3=0.5335 (paper .5369), 3v4=0.514 (paper .5174), 4v5=0.5184 (paper .5175).


I'm wondering if the paper's Mistral values were averaged across multiple runs or interpolated somehow, or if there's a separate unregistered experiment. Let me search for any newer Mistral variants or "10k" versions that might match better, and I should also dig into the OLMo discrepancy more carefully.

Now checking Pythia-6.9B and Gemma-2B against the registry—Pythia matches perfectly across all four metrics, though the paper shows a blank for 4v5 which the registry also lacks. For Gemma-2B, I'm comparing the paper's five values against what's in the registry with C...

Looking at the confidence intervals and point estimates, the paper's 0v1 value of .953 aligns with the registry's 0.9534, and 1v2 matches at 0.5981, while I'm still verifying the remaining comparisons. Looking at the Qwen-scored values from that experiment, they don't align with the paper's Gemma results either. The exp_gemma2b_depth numbers seem to match the paper more closely when accounting for rounding differences, though there are still small discrepancies in a couple of the pairwise comparisons. I should check whether exp_gemma2b_depth has the full precision values and compare the confidence intervals more carefully to see if they're consistent with what's reported. Now I'm mapping out which experiment corresponds to each model in the table — Qwen-rw comes from the bootstrap CI experiment, Pythia from the depth study, and I need to track down the sources for OLMo, the various Qwen variants, LLaMA, and Mistral to ensure I'm pulling AUC and confidence intervals from the right places.

Let me systematically verify each value against the experiments, and I should also check if there's an OLMo result matching .9860 exactly. I'm also going to look more carefully at the confidence interval data in Table 10 to make sure I'm reading the bounds correctly.

Looking at the table rows, I can see the 1v2 comparison shows Mistral-7B at .5750 without a confidence interval, while Pythia-6.9B is at .5955 also without one. Now I'm examining the 2v3 comparison row to continue tracking these values.

Generating markdown table...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "45feec99-17e4-48b1-b64e-c43d881c0091",
  "isSidechain": false,
  "requestId": "req_011CbKPhABPTMTFvMFtWU71E",
  "type": "assistant",
  "uuid": "69f43e2c-d8e6-4892-8f57-bd0321d92258",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014MiMokpFjNTt9KzpPxrg4g",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1567,
      "cache_read_input_tokens": 70636,
      "output_tokens": 3013,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1567,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3013,
          "cache_read_input_tokens": 70636,
          "cache_creation_input_tokens": 1567,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1567
          },
          "type": "message"
        }
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

_source line 56 · 2026-05-23T11:06:46.094Z_

<details open><summary>🔧 Tool call — Bash · `toolu_014wZhmqV3KuiEX62sxAiN1v`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get all OLMo experiments\nprint('=== OLMo experiments ===')\nfor eid, exp in sorted(exps.items()):\n    if 'olmo' in eid.lower():\n        metrics = exp.get('metrics', {})\n        pauc = metrics.get('pairwise_auc', {})\n        status = exp.get('status', '')\n        if status != 'DONE':\n            continue\n        print(f'{eid}:')\n        if pauc:\n            print(f'  pairwise_auc: {pauc}')\n        # Check for individual AUC keys\n        for k in ['0v1_auc', '1v2_auc', 'AUC_0v1']:\n            if k in metrics:\n                print(f'  {k}: {metrics[k]}')\n        ci = metrics.get('bootstrap_ci', {})\n        if ci:\n            print(f'  bootstrap_ci: {json.dumps(ci, indent=4)[:500]}')\n        print()\n\n# Get Pythia CI for 2v3 \nprint('=== Pythia 2v3 CI ===')\nfor eid in ['exp_001_pythia_depth', 'exp_C_permutation_10k']:\n    if eid in exps:\n        exp = exps[eid]\n        metrics = exp.get('metrics', {})\n        ci = metrics.get('bootstrap_ci', {})\n        print(f'{eid} CI: {json.dumps(ci, indent=2)[:1000]}')\n        print()\n\" 2>&1\n",
  "description": "Get OLMo and Pythia CI data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "69f43e2c-d8e6-4892-8f57-bd0321d92258",
  "isSidechain": false,
  "requestId": "req_011CbKPhABPTMTFvMFtWU71E",
  "type": "assistant",
  "uuid": "81b63334-3600-4c0f-99eb-f06972583bc0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014MiMokpFjNTt9KzpPxrg4g",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1567,
      "cache_read_input_tokens": 70636,
      "output_tokens": 3013,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1567,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3013,
          "cache_read_input_tokens": 70636,
          "cache_creation_input_tokens": 1567,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1567
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-23T11:06:46.188Z_

<details><summary>↩ Tool result · `toolu_014wZhmqV3KuiEX62sxAiN1v`</summary>

```text
=== OLMo experiments ===
exp_002_olmo_depth:
  pairwise_auc: {'0v1': 0.9861, '1v2': 0.5001, '2v3': 0.4972, '3v4': 0.5034, '4v5': 0.4971}

exp_arXiv_olmo:

exp_olmo1b_10k:
  pairwise_auc: {'0v1': 0.9871, '1v2': 0.4984, '2v3': 0.5059, '3v4': 0.5061, '4v5': 0.5074}

exp_olmo1b_c4_rerun:
  0v1_auc: 0.986
  1v2_auc: 0.508

exp_olmo_retrain_chain:

exp_olmo_retrain_v3:
  pairwise_auc: {'0v1': 0.9873, '1v2': 0.8889, '2v3': 0.7036, '3v4': 0.6817}

exp_wiki_olmo:

exp_wiki_olmo_v2:

=== Pythia 2v3 CI ===
exp_001_pythia_depth CI: {
  "1v2": {
    "auc_oof": 0.6072,
    "boot_mean": 0.6073,
    "boot_std": 0.005,
    "ci_95": [
      0.5975,
      0.6172
    ],
    "ci_995_bonferroni": [
      0.5934,
      0.621
    ],
    "perm_p": 0.0001,
    "bonferroni_pass": false
  }
}

exp_C_permutation_10k CI: {}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "81b63334-3600-4c0f-99eb-f06972583bc0",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "8cc92469-6043-46fd-b480-4b1ea29ff4ed",
  "toolUseResult": {
    "stdout": "=== OLMo experiments ===\nexp_002_olmo_depth:\n  pairwise_auc: {'0v1': 0.9861, '1v2': 0.5001, '2v3': 0.4972, '3v4': 0.5034, '4v5': 0.4971}\n\nexp_arXiv_olmo:\n\nexp_olmo1b_10k:\n  pairwise_auc: {'0v1': 0.9871, '1v2': 0.4984, '2v3': 0.5059, '3v4': 0.5061, '4v5': 0.5074}\n\nexp_olmo1b_c4_rerun:\n  0v1_auc: 0.986\n  1v2_auc: 0.508\n\nexp_olmo_retrain_chain:\n\nexp_olmo_retrain_v3:\n  pairwise_auc: {'0v1': 0.9873, '1v2': 0.8889, '2v3': 0.7036, '3v4': 0.6817}\n\nexp_wiki_olmo:\n\nexp_wiki_olmo_v2:\n\n=== Pythia 2v3 CI ===\nexp_001_pythia_depth CI: {\n  \"1v2\": {\n    \"auc_oof\": 0.6072,\n    \"boot_mean\": 0.6073,\n    \"boot_std\": 0.005,\n    \"ci_95\": [\n      0.5975,\n      0.6172\n    ],\n    \"ci_995_bonferroni\": [\n      0.5934,\n      0.621\n    ],\n    \"perm_p\": 0.0001,\n    \"bonferroni_pass\": false\n  }\n}\n\nexp_C_permutation_10k CI: {}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "81b63334-3600-4c0f-99eb-f06972583bc0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 58_

```json
{
  "type": "last-prompt",
  "leafUuid": "8cc92469-6043-46fd-b480-4b1ea29ff4ed",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 59_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 60 · 2026-05-23T11:09:04.925Z_

<details><summary>Logged reasoning block</summary>

```text
OK, so for Pythia, the bootstrap CI only exists for 1v2. The paper shows CIs for 1v2 and 2v3. Let me check exp_C_permutation_10k and exp_bootstrap_10k for more CI data. Actually, the paper lists CIs for Pythia 2v3 as [.534,.554]. Let me check if there's another experiment with these values.

Actually, looking at the paper Table 2 again, it seems that the Pythia CIs for 2v3 [.534,.554] may come from a different source. Let me search more broadly.


I'm noticing that exp_007_bootstrap_ci has different Pythia values than exp_001 — the self-scored results in exp_007 don't match the Qwen-scored results the paper actually uses. So I need to figure out where those 2v3 CIs are coming from.

Let me trace back through the experiments to see which ones contain the bootstrap confidence intervals for each model's comparison. The main point estimates in Table 2 seem to come from different sources: Qwen-rewrite from exp_007, Pythia from exp_001, OLMo from exp_002, and I need to identify where the rest are coming from.

The confidence intervals are trickier—exp_007 has them for the Qwen variants, exp_001 has them for Pythia 1v2, and exp_004 for Qwen-7B. But the OLMo and Pythia 2v3 confidence intervals might be computed outside the registry or in experiments I haven't found yet. Let me systematically verify each value in Table 2 against what's actually in the registry.

Starting with the 0v1 comparisons: Qwen-rw, Pythia, and Qwen-cont all match perfectly, but OLMo shows a tiny discrepancy—the paper has .9860 while the registry shows 0.9861, which is off by 0.0001. Qwen-7B also checks out. Moving into the 1v2 row, Qwen-rw and Pythia both match, but I need to continue checking the rest. Continuing through the remaining rows, I'm seeing more matches across the board—Qwen-cont and Qwen-7B both align perfectly in row 3v4, while Qwen-rw and Pythia also check out. OLMo shows another discrepancy here, this time off by 0.0010, and I'm still working through the Qwen-7B bootstrap values. Checking the confidence intervals for the remaining comparisons—Pythia and Qwen-cont both match their paper values when rounded to three decimal places, while OLMo's interval for 1v2 isn't in the registry so I need to track down that source. Moving on to verify the 2v3 intervals now. Looking at the last two OLMo discrepancies, they match the rerun experiment exactly, suggesting the paper might be pulling from different experiment versions—the original exp_002 for the first two OLMo rows and the rerun for the later ones. The note about exp_002 mentions it was updated to use Qwen cross-scoring, which could explain why the registry values differ from what's in the paper. Now I'm checking the Qwen-base results from exp_016_base_vs_instruct against the paper values, and most of them match up when accounting for rounding—the 0v1, 1v2, and 2v3 comparisons all check out, though I need to verify the remaining values.

For LLaMA-8B from exp_018_llama8b_depth, all five comparisons match perfectly with the bootstrap confidence intervals in the registry, which is a good sign.

Moving on to Mistral-7B...

the paper reports specific accuracy values across the five depth comparisons, but neither of my experimental runs—whether self-scored or cross-scored by Qwen—align with those paper values. All five metrics diverge from what was published, which is concerning and suggests something fundamental might be off with how I'm reproducing this model's results.

Now looking at other models in the registry, Pythia-6.9B shows perfect alignment with the paper across all four reported metrics, which is reassuring. Gemma-2B's values are also matching the paper so far, though the registry entry appears incomplete. I'm wondering if the registry might be storing limited precision values, so 0.503 could actually represent 0.5033 underneath. Let me search through the experiments to see if there's a Gemma configuration that produces that 0.5033 value for the 3v4 comparison, or if there's a different experimental setup being used. Checking the confidence intervals for the remaining Qwen-base fold comparisons and they all match up correctly with the experimental data. Moving on to verify LLaMA-8B's intervals across the folds. Continuing to verify the Gemma-2B results—I've confirmed the first pair, but I'm missing source data for the 0v1 comparison and need to track down where the 2v3 through 4v5 ranges came from. I notice the 3v4 and 4v5 results are identical, which seems suspicious. Now I'm checking the experimental setup table to see what models and configurations were actually used in the study. I'm verifying the model names are correct—they all match what I know about these models, with the parameter counts embedded in the names themselves. Now I'm cross-checking the numerical values between Table 2 and Table 10 for the five overlapping configurations to ensure consistency, and so far the first few comparisons are matching perfectly. The Mistral-7B discrepancy is significant—the paper reports values that don't align with either the self-scored experiment (exp_019) or the cross-scored version (exp_019b), with differences ranging from about 0.06 to 0.16 across comparisons. For OLMo, there's a minor data source issue where the paper values match the C4 rerun experiment rather than exp_002, suggesting possible confusion about which dataset was actually used. I'm wondering if the paper used a different experiment run or dataset entirely—maybe the wiki or code domain instead. Checking those experiments, the wiki data is empty but the code domain shows different AUC values that also don't match the paper's reported numbers.

Let me reconsider the table structure itself—perhaps I'm misinterpreting the column layout in Table 10 and the model assignments are different than I thought. Continuing to verify the column alignment by counting the ampersands in the data row to ensure Mistral-7B values are in the correct positions. I'm finishing the table with Mistral-7B at .9170 and Gemma-2B at .953, confirming the paper's 0v1 results. Since none of the registry experiments match these values, I'm considering whether the paper used an intermediary calculation or a different experimental setup—there's no 10k variant for Mistral, just the standard experiments across different data sources.

Looking at the paper's text about Mistral's 1v2 AUC range of 0.500–0.598, I'm checking whether the observed .5750 falls within that bound and whether there's a different scoring approach or blend that could explain the discrepancy. The range 0.500--0.598 does cover all four models when I account for rounding: OLMo at .5001, Mistral at .575, Pythia-6.9B at .5955 (rounds to .596), and Gemma at .5981 (rounds to .598). Now I'm wondering if the Mistral values in the paper might be incorrect, so I should check what the actual values should be based on the registry data, particularly since the paper uses Qwen cross-scoring for some models.

Looking at the Qwen-scored Mistral experiment, I get different numbers than what's reported: my values are 0v1=0.9209, 1v2=0.5695, 2v3=0.5335, 3v4=0.514, 4v5=0.5184, but the paper shows 0v1=.9170, 1v2=.5750, 2v3=.5369, 3v4=.5174, 4v5=.5175. They're close enough that they could come from the same experiment with different random seeds or cross-validation splits, but they don't match exactly.

I'm wondering if maybe there's a bootstrap version I'm missing, or if the paper values come from a newer re-run of the experiment. The differences are small but consistent enough that they're not just rounding errors. Looking at the OLMo results too, the paper's 3v4=.5024 and 4v5=.4942 match the exp_olmo1b_c4_rerun numbers exactly, not the exp_002 registry entry, which suggests the registry might not have been fully updated when that experiment was re-run.

Now I'm checking a few more targeted sources—looking at what the bootstrap and permutation experiments contain, whether the Gemma confidence intervals come from exp_gemma2b_10k, and what the standard deviation values are in the Mistral cross-scorer experiment. Once I've verified these last few data points, I should have enough to compile the full audit report.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8cc92469-6043-46fd-b480-4b1ea29ff4ed",
  "isSidechain": false,
  "requestId": "req_011CbKPmD4PRUrqo3wt2jJpm",
  "type": "assistant",
  "uuid": "d4567a35-4a1d-4b01-8045-153371c9fd78",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdn7cFvUZaE8mNyK4UpudF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3494,
      "cache_read_input_tokens": 72203,
      "output_tokens": 8935,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3494,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8935,
          "cache_read_input_tokens": 72203,
          "cache_creation_input_tokens": 3494,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3494
          },
          "type": "message"
        }
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

_source line 61 · 2026-05-23T11:09:14.318Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01VYTNe3a5keqvpEYcGe9oX9`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Full dump of Gemma 10k experiment\nprint('=== exp_gemma2b_10k FULL ===')\nexp = exps.get('exp_gemma2b_10k', {})\nmetrics = exp.get('metrics', {})\nprint(json.dumps(metrics, indent=2)[:2000])\n\n# Full dump of exp_gemma2b_depth\nprint()\nprint('=== exp_gemma2b_depth FULL ===')\nexp = exps.get('exp_gemma2b_depth', {})\nmetrics = exp.get('metrics', {})\nprint(json.dumps(metrics, indent=2)[:2000])\n\n# Check if there's a seed_gemma or another gemma experiment\nprint()\nprint('=== All Gemma experiments ===')\nfor eid, exp in sorted(exps.items()):\n    if 'gemma' in eid.lower():\n        status = exp.get('status', '')\n        metrics = exp.get('metrics', {})\n        pauc = metrics.get('pairwise_auc', metrics.get('pairwise_auc_qwen', {}))\n        print(f'{eid} [{status}]: {pauc}')\n\n# Also check seed_gemma experiment\nprint()\nprint('=== seed_gemma27b_c4_s42 ===')\nexp = exps.get('seed_gemma27b_c4_s42', {})\nmetrics = exp.get('metrics', {})\nprint(json.dumps(metrics, indent=2)[:1000])\n\" 2>&1\n",
  "description": "Get Gemma experiment details"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d4567a35-4a1d-4b01-8045-153371c9fd78",
  "isSidechain": false,
  "requestId": "req_011CbKPmD4PRUrqo3wt2jJpm",
  "type": "assistant",
  "uuid": "edc45405-a8d6-4fa3-b57c-474ced02fbf4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdn7cFvUZaE8mNyK4UpudF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3494,
      "cache_read_input_tokens": 72203,
      "output_tokens": 8935,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3494,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8935,
          "cache_read_input_tokens": 72203,
          "cache_creation_input_tokens": 3494,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3494
          },
          "type": "message"
        }
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

_source line 62 · 2026-05-23T11:09:14.418Z_

<details><summary>↩ Tool result · `toolu_01VYTNe3a5keqvpEYcGe9oX9`</summary>

```text
=== exp_gemma2b_10k FULL ===
{
  "K_star_self": 2,
  "K_star_qwen": 2,
  "scorer": "Qwen2.5-1.5B-Instruct (cross-scored)",
  "pairwise_auc_self": {
    "0v1": 0.9817,
    "1v2": 0.643,
    "2v3": 0.555,
    "3v4": 0.5173,
    "4v5": 0.5101
  },
  "pairwise_auc_qwen": {
    "0v1": 0.9533,
    "1v2": 0.6099,
    "2v3": 0.5409,
    "3v4": 0.5174,
    "4v5": 0.5158
  },
  "bootstrap_ci_1v2": {
    "auc_oof": 0.6099,
    "boot_std": 0.0034,
    "ci_95": [
      0.6031,
      0.6167
    ],
    "ci_995_bonferroni_pct": [
      0.5998,
      0.6192
    ],
    "ci_995_bonferroni_norm": [
      0.6003,
      0.6196
    ],
    "perm_p": 0.0001,
    "bonferroni_pass_pct": false,
    "bonferroni_pass_norm": true
  },
  "note": "5K K*=1 (1v2=0.5981), 10K Qwen cross-scored K*=2 (1v2=0.6099). Bonferroni split: percentile FAIL (0.5998), normal PASS (0.6003). Extremely borderline."
}

=== exp_gemma2b_depth FULL ===
{
  "k_star": 1,
  "pairwise_auc": {
    "0v1": 0.9534,
    "1v2": 0.5981,
    "2v3": 0.5342,
    "3v4": 0.503,
    "4v5": 0.5026
  },
  "pairwise_auc_std": {
    "0v1": 0.003,
    "1v2": 0.008,
    "2v3": 0.013,
    "3v4": 0.003,
    "4v5": 0.013
  },
  "bootstrap_ci_1v2": {
    "ci_lower": 0.5882,
    "ci_upper": 0.6076
  },
  "jsd": {
    "0v1": 0.09882,
    "1v2": 0.008852,
    "2v3": 0.004904,
    "3v4": 0.003742,
    "4v5": 0.003167
  },
  "ordinal_mae": 1.3152,
  "ordinal_accuracy": 0.3321,
  "note": "K*=1, NOT borderline K*=2. 1v2 AUC=0.5981 < theta=0.60. CI upper=0.6076 crosses theta but point estimate below."
}

=== All Gemma experiments ===
exp_gemma27b_c4 [PREPARING]: {}
exp_gemma2b_10k [DONE]: {'0v1': 0.9533, '1v2': 0.6099, '2v3': 0.5409, '3v4': 0.5174, '4v5': 0.5158}
exp_gemma2b_depth [DONE]: {'0v1': 0.9534, '1v2': 0.5981, '2v3': 0.5342, '3v4': 0.503, '4v5': 0.5026}
seed_gemma27b_c4_s42 [DONE]: {'0v1': 0.8874, '1v2': 0.5894}

=== seed_gemma27b_c4_s42 ===
{
  "K_star": 1,
  "scorer": "Qwen2.5-1.5B-Instruct (cross-scored)",
  "pairwise_auc_self": {
    "0v1": 0.9695,
    "1v2": 0.6196,
    "2v3": 0.5388,
    "3v4": 0.5069,
    "4v5": 0.5124
  },
  "pairwise_auc_qwen": {
    "0v1": 0.8874,
    "1v2": 0.5894
  },
  "note": "Self-scored K*=2 (1v2=0.6196), Qwen cross-scored K*=1 (1v2=0.5894 < \u03b8=0.60). Self\u2192Cross inflation: 1v2 \u0394=-3.0pp, 0v1 \u0394=-8.2pp."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "edc45405-a8d6-4fa3-b57c-474ced02fbf4",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "ce4dfda1-7345-4ca5-96be-e74eb6b076be",
  "toolUseResult": {
    "stdout": "=== exp_gemma2b_10k FULL ===\n{\n  \"K_star_self\": 2,\n  \"K_star_qwen\": 2,\n  \"scorer\": \"Qwen2.5-1.5B-Instruct (cross-scored)\",\n  \"pairwise_auc_self\": {\n    \"0v1\": 0.9817,\n    \"1v2\": 0.643,\n    \"2v3\": 0.555,\n    \"3v4\": 0.5173,\n    \"4v5\": 0.5101\n  },\n  \"pairwise_auc_qwen\": {\n    \"0v1\": 0.9533,\n    \"1v2\": 0.6099,\n    \"2v3\": 0.5409,\n    \"3v4\": 0.5174,\n    \"4v5\": 0.5158\n  },\n  \"bootstrap_ci_1v2\": {\n    \"auc_oof\": 0.6099,\n    \"boot_std\": 0.0034,\n    \"ci_95\": [\n      0.6031,\n      0.6167\n    ],\n    \"ci_995_bonferroni_pct\": [\n      0.5998,\n      0.6192\n    ],\n    \"ci_995_bonferroni_norm\": [\n      0.6003,\n      0.6196\n    ],\n    \"perm_p\": 0.0001,\n    \"bonferroni_pass_pct\": false,\n    \"bonferroni_pass_norm\": true\n  },\n  \"note\": \"5K K*=1 (1v2=0.5981), 10K Qwen cross-scored K*=2 (1v2=0.6099). Bonferroni split: percentile FAIL (0.5998), normal PASS (0.6003). Extremely borderline.\"\n}\n\n=== exp_gemma2b_depth FULL ===\n{\n  \"k_star\": 1,\n  \"pairwise_auc\": {\n    \"0v1\": 0.9534,\n    \"1v2\": 0.5981,\n    \"2v3\": 0.5342,\n    \"3v4\": 0.503,\n    \"4v5\": 0.5026\n  },\n  \"pairwise_auc_std\": {\n    \"0v1\": 0.003,\n    \"1v2\": 0.008,\n    \"2v3\": 0.013,\n    \"3v4\": 0.003,\n    \"4v5\": 0.013\n  },\n  \"bootstrap_ci_1v2\": {\n    \"ci_lower\": 0.5882,\n    \"ci_upper\": 0.6076\n  },\n  \"jsd\": {\n    \"0v1\": 0.09882,\n    \"1v2\": 0.008852,\n    \"2v3\": 0.004904,\n    \"3v4\": 0.003742,\n    \"4v5\": 0.003167\n  },\n  \"ordinal_mae\": 1.3152,\n  \"ordinal_accuracy\": 0.3321,\n  \"note\": \"K*=1, NOT borderline K*=2. 1v2 AUC=0.5981 < theta=0.60. CI upper=0.6076 crosses theta but point estimate below.\"\n}\n\n=== All Gemma experiments ===\nexp_gemma27b_c4 [PREPARING]: {}\nexp_gemma2b_10k [DONE]: {'0v1': 0.9533, '1v2': 0.6099, '2v3': 0.5409, '3v4': 0.5174, '4v5': 0.5158}\nexp_gemma2b_depth [DONE]: {'0v1': 0.9534, '1v2': 0.5981, '2v3': 0.5342, '3v4': 0.503, '4v5': 0.5026}\nseed_gemma27b_c4_s42 [DONE]: {'0v1': 0.8874, '1v2': 0.5894}\n\n=== seed_gemma27b_c4_s42 ===\n{\n  \"K_star\": 1,\n  \"scorer\": \"Qwen2.5-1.5B-Instruct (cross-scored)\",\n  \"pairwise_auc_self\": {\n    \"0v1\": 0.9695,\n    \"1v2\": 0.6196,\n    \"2v3\": 0.5388,\n    \"3v4\": 0.5069,\n    \"4v5\": 0.5124\n  },\n  \"pairwise_auc_qwen\": {\n    \"0v1\": 0.8874,\n    \"1v2\": 0.5894\n  },\n  \"note\": \"Self-scored K*=2 (1v2=0.6196), Qwen cross-scored K*=1 (1v2=0.5894 < \\u03b8=0.60). Self\\u2192Cross inflation: 1v2 \\u0394=-3.0pp, 0v1 \\u0394=-8.2pp.\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "edc45405-a8d6-4fa3-b57c-474ced02fbf4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 63_

```json
{
  "type": "last-prompt",
  "leafUuid": "ce4dfda1-7345-4ca5-96be-e74eb6b076be",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 64_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 65 · 2026-05-23T11:10:18.341Z_

<details><summary>Logged reasoning block</summary>

```text
OK, so now I see that the paper's Gemma values come from exp_gemma2b_depth (5K sample, Qwen cross-scored). The 3v4=0.503 in registry vs .5033 in paper — the difference is 0.0003 and likely due to storage precision. 4v5=0.5026 vs .5025 — off by 0.0001.

These are very minor and could be rounding/precision issues in the registry storage. Let me flag them but they're not critical.

Now, the most critical issue is the Mistral-7B values. 

Let me dig into the paper's methodology section to see if there's any clue about how Mistral was evaluated — whether it was self-scored, cross-scored, or maybe averaged from both approaches. The experiments section mentions using the OBD-LightGBM classifier with a 15-dimensional feature set and 5,000 texts per depth level, but I need to find the specific details about Mistral's scoring method.

Looking at the cross-scored values from my experiment run, I'm getting 0.9209 and 0.5695, but the paper reports 0.9170 and 0.5750 — they're close but consistently off by about 0.005. This gap suggests the paper's values came from a separate run, possibly with different parameters, feature configurations, or cross-validation splits. Since neither of my experiments matches the published numbers, it seems likely there was a final unregistered run of Mistral cross-scoring that produced the paper's results, which is a real tracking problem.

Now checking the OLMo footnote consistency — the paper rounds 0.4973 to 0.497 and 0.5024 to 0.502, giving a delta of 0.005, which checks out. Moving on to verify the model parameter counts listed in Table 1.

The parameter sizes all match their standard model names — Qwen2.5-1.5B is indeed 1.5B, Pythia-1.4B is 1.4B, OLMo-1B is 1B, and Qwen2.5-7B is 7B, so those are correct.

Now looking at the Mistral discrepancies between the experiment and paper results across the five comparisons, I'm seeing consistent small deltas ranging from about 0.003 to 0.005 in absolute value, with some results slightly higher in the experiment and others slightly lower.

The 1v2 comparison stands out as the largest difference, where the paper actually reports higher values than the registry, which is interesting given that the paper still classifies Mistral as K*=1. This inconsistency is concerning because I can't definitively determine which values are correct — the paper results might come from a separate legitimate experiment that wasn't registered. I should flag this discrepancy and recommend using the registry values as the authoritative source.

For OLMo, there's a mixing of results from different experiments in the paper — some values match the rerun experiment while others match exp_002, which suggests the paper may have cherry-picked results from different runs rather than using a single consistent experiment. recent values across both experiments — mixing the rerun data for 3v4 and 4v5 with the exp_002 values for the earlier comparisons.

For the audit, I need to flag that exp_002 should be updated to align with the paper, and note that the Mistral discrepancies can't be resolved without knowing which experiment is the authoritative source. Since neither registry entry matches the paper's Mistral values exactly, I should report this as requiring manual verification rather than making an edit based on incomplete information. Let me take another look at the Mistral numbers to see if there's a pattern I'm missing — maybe the paper values are derived differently or there's a transcription error somewhere. are:

1. **Table 1**: All model names and parameter counts are correct.
2. **Table 2 vs Table 10 overlap**: All 5 overlapping configs are perfectly consistent between tables.
3. **Table 2 and 10 vs Registry**: Most values match, with these exceptions:
   - OLMo: 3v4 and 4v5 don't match exp_002 (registry needs update)
   - Mistral-7B: ALL values don't match any registry experiment (major issue)
   - Gemma-2B: Minor rounding discrepancies in 3v4 and 4v5

For the Mistral issue, since neither exp_019 nor exp_019b matches the paper values and the paper uses Qwen cross-scoring consistently, I should update the Mistral values to exp_019b's cross-scored results.

For OLMo, the paper values might actually be from a more recent run and could be correct—the registry entry exp_002 should be updated instead. The Gemma differences are negligible rounding artifacts, so those don't need fixing. But I need to double-check the OLMo 0v1 value since the paper shows .9860 while exp_002 has .9861 and the rerun shows .986 with limited precision—I should verify what the actual value is. Looking at the pattern across all five values, four of them match the rerun data while only one aligns with exp_002, which strongly suggests the paper is drawing from the rerun experiment. The discrepancy in the 1v2 value—where the paper shows .5001 matching exp_002 instead of the rerun's 0.508—is puzzling and might indicate that particular comparison was re-evaluated separately or the rerun had different configuration for that specific pair.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ce4dfda1-7345-4ca5-96be-e74eb6b076be",
  "isSidechain": false,
  "requestId": "req_011CbKPx8nU93vipSzJXVXPh",
  "type": "assistant",
  "uuid": "c16a8351-98bb-46ad-b26f-e422dd8c1d2a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013jTTjqcU5Z2CUNtPftcBFx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10273,
      "cache_read_input_tokens": 75697,
      "output_tokens": 3592,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10273,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3592,
          "cache_read_input_tokens": 75697,
          "cache_creation_input_tokens": 10273,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10273
          },
          "type": "message"
        }
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

_source line 66 · 2026-05-23T11:10:29.612Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01FkdNuAvgxMBd21hbQ43dno`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Full OLMo rerun details\nprint('=== exp_olmo1b_c4_rerun FULL ===')\nexp = exps.get('exp_olmo1b_c4_rerun', {})\nprint(json.dumps(exp, indent=2)[:3000])\nprint()\n\n# Check any experiment with Mistral values near paper\n# Try finding matching values for Mistral 1v2=0.575\nprint('=== All experiments with 1v2 in 0.57-0.58 ===')\nfor eid, exp in sorted(exps.items()):\n    metrics = exp.get('metrics', {})\n    pauc = metrics.get('pairwise_auc', {})\n    if isinstance(pauc, dict):\n        v12 = pauc.get('1v2', None)\n        if v12 and isinstance(v12, (int, float)) and 0.570 <= v12 <= 0.580:\n            print(f'{eid}: 1v2={v12}, 0v1={pauc.get(\\\"0v1\\\",\\\"N/A\\\")}, full={pauc}')\n\n    # Also check individual key formats\n    v12b = metrics.get('AUC_1v2', metrics.get('1v2_auc', None))\n    if v12b and isinstance(v12b, (int, float)) and 0.570 <= v12b <= 0.580:\n        print(f'{eid}: 1v2={v12b} (alt key format)')\n\" 2>&1\n",
  "description": "Get OLMo rerun details and search for Mistral values"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c16a8351-98bb-46ad-b26f-e422dd8c1d2a",
  "isSidechain": false,
  "requestId": "req_011CbKPx8nU93vipSzJXVXPh",
  "type": "assistant",
  "uuid": "04a1371b-4297-418d-8f36-b0f59ff214eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013jTTjqcU5Z2CUNtPftcBFx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10273,
      "cache_read_input_tokens": 75697,
      "output_tokens": 3592,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10273,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3592,
          "cache_read_input_tokens": 75697,
          "cache_creation_input_tokens": 10273,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10273
          },
          "type": "message"
        }
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

_source line 67 · 2026-05-23T11:10:29.699Z_

<details><summary>↩ Tool result · `toolu_01FkdNuAvgxMBd21hbQ43dno`</summary>

```text
=== exp_olmo1b_c4_rerun FULL ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-21T11:10:33.358Z",
  "updated_at": "2026-05-21T11:11:13.525Z",
  "hypothesis": "OLMo-1B C4 depth chain \u53ef\u590d\u73b0\u6027\u9a8c\u8bc1\uff1a\u6807\u51c6\u5316 pipeline\uff08Qwen-1.5B scorer\uff09\u4e0b K* \u503c\u4e0e\u4e3b\u8868\u4e00\u81f4\u3002",
  "conclusion": "negative",
  "metrics": {
    "0v1_auc": 0.986,
    "1v2_auc": 0.508,
    "2v3_auc": 0.4973,
    "3v4_auc": 0.5024,
    "4v5_auc": 0.4942,
    "kstar_at_060": 1,
    "main_table_1v2": 0.6145,
    "delta": -0.1065
  },
  "spec": {
    "command": "python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/models--allenai--OLMo-1B-hf/... --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --no_sample",
    "server": "cqa1-22115",
    "gpu": [
      "cuda:1"
    ],
    "data_path": "data/exp_olmo1b_c4_rerun",
    "data_count": 5000,
    "model_name": "allenai/OLMo-1B-hf",
    "seed": "default",
    "checkpoint_path": "results/exp_olmo1b_c4_rerun/",
    "log_path": "results/exp_olmo1b_c4_rerun/experiment_config.json",
    "checkpoint_source": "N/A",
    "eval_data": "N/A"
  },
  "completed_at": "2026-05-21T11:11:13.525Z"
}

=== All experiments with 1v2 in 0.57-0.58 ===
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "04a1371b-4297-418d-8f36-b0f59ff214eb",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "6a884ee6-134e-4c0d-aca5-1d2c99864fa3",
  "toolUseResult": {
    "stdout": "=== exp_olmo1b_c4_rerun FULL ===\n{\n  \"status\": \"DONE\",\n  \"retry_count\": 0,\n  \"created_at\": \"2026-05-21T11:10:33.358Z\",\n  \"updated_at\": \"2026-05-21T11:11:13.525Z\",\n  \"hypothesis\": \"OLMo-1B C4 depth chain \\u53ef\\u590d\\u73b0\\u6027\\u9a8c\\u8bc1\\uff1a\\u6807\\u51c6\\u5316 pipeline\\uff08Qwen-1.5B scorer\\uff09\\u4e0b K* \\u503c\\u4e0e\\u4e3b\\u8868\\u4e00\\u81f4\\u3002\",\n  \"conclusion\": \"negative\",\n  \"metrics\": {\n    \"0v1_auc\": 0.986,\n    \"1v2_auc\": 0.508,\n    \"2v3_auc\": 0.4973,\n    \"3v4_auc\": 0.5024,\n    \"4v5_auc\": 0.4942,\n    \"kstar_at_060\": 1,\n    \"main_table_1v2\": 0.6145,\n    \"delta\": -0.1065\n  },\n  \"spec\": {\n    \"command\": \"python scripts/run_pipeline.py --model_path /root/autodl-tmp/.hf_cache/models--allenai--OLMo-1B-hf/... --scorer_path /root/autodl-tmp/.hf_cache/Qwen/Qwen2___5-1___5B --num_samples 5000 --max_depth 5 --batch_size 8 --generation_mode continuation --no_sample\",\n    \"server\": \"cqa1-22115\",\n    \"gpu\": [\n      \"cuda:1\"\n    ],\n    \"data_path\": \"data/exp_olmo1b_c4_rerun\",\n    \"data_count\": 5000,\n    \"model_name\": \"allenai/OLMo-1B-hf\",\n    \"seed\": \"default\",\n    \"checkpoint_path\": \"results/exp_olmo1b_c4_rerun/\",\n    \"log_path\": \"results/exp_olmo1b_c4_rerun/experiment_config.json\",\n    \"checkpoint_source\": \"N/A\",\n    \"eval_data\": \"N/A\"\n  },\n  \"completed_at\": \"2026-05-21T11:11:13.525Z\"\n}\n\n=== All experiments with 1v2 in 0.57-0.58 ===",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "04a1371b-4297-418d-8f36-b0f59ff214eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 68 · 2026-05-23T11:10:29.702Z_

```json
{
  "parentUuid": "6a884ee6-134e-4c0d-aca5-1d2c99864fa3",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "6aff20ef-4f5d-4b67-b1f2-8d24633fe5b5",
  "timestamp": "2026-05-23T11:10:29.702Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 69 · 2026-05-23T11:11:54.761Z_

<details><summary>Logged reasoning block</summary>

```text
No experiment has 1v2 in the range 0.570-0.580. This confirms that the paper's Mistral 1v2=.5750 doesn't come from any registered experiment.

For OLMo, the rerun used `--no_sample` which likely means it used greedy decoding, not nucleus sampling. But the original exp_002 and the paper use nucleus sampling. The rerun also has `main_table_1v2: 0.6145` which is the self-scored value, and `delta: -0.1065` showing the drop from self to Qwen-scoring.


The rerun's 1v2=0.508 is substantially lower than exp_002's 0.5001, likely due to the different decoding strategy. But here's the issue: the paper reports OLMo 1v2=.5001 matching exp_002, yet its 3v4 and 4v5 values match the rerun instead. So the paper is inconsistently pulling results from two different experiments with different decoding methods.

Looking more closely though, the 0v1_auc and 2v3 scores are nearly identical between the rerun and exp_002, which suggests the `--no_sample` flag might not be about greedy decoding at all. More likely, the texts were already generated and the rerun just re-executed the classification pipeline on the same data, with `--no_sample` controlling something about the sampling process itself rather than text generation. The small discrepancies probably come from different cross-validation splits or feature extraction variations.

I'm getting too caught up in the details here — let me just focus on what I've actually found and move forward.

I need to compile the final audit table, but first I want to double-check something about the paper's model specifications. The paper lists "Qwen2.5-7B" in Table 1 but the footnote specifies the generator as "Qwen2.5-7B (fp16)" and scorer as "Qwen2.5-1.5B", so I should verify this matches the exp_004_7b_crossscale experiment.

The key findings are clear now: Mistral-7B has a major issue with all five AUC values in Tables 2 and 10 not matching any registry experiment, while OLMo's 3v4 and 4v5 values don't align with the primary exp_002_olmo_depth entry but instead match exp_olmo1b_c4_rerun. Time to produce the output.

Gemma-2B shows only minor precision differences in the 3v4 and 4v5 values, Table 1 is completely correct across all six configs, and the overlapping entries between Tables 2 and 10 are perfectly consistent. For Mistral, the closest match is exp_019b_mistral_cross_scorer, and since the task asks me to fix errors directly, I should update the paper values to match this experiment rather than just flagging it. OLMo registry needs updating rather than a paper correction. Let me verify the confidence intervals more carefully across the tables to ensure consistency. Checking a few entries like Qwen and Pythia's CI values against the registry shows they round correctly to the paper values, so those are fine.

Now I'm examining the specific text ranges mentioned in the paper body, like the 1v2 AUC range for K*=1 models, to make sure those bounds match what's actually in the experimental data.

For the LLaMA-3.1-8B entry confirming K*=2, I'm noticing a discrepancy: the paper text states 0v1 AUC as 0.9225, but the registry shows 0.9224 from the bootstrap CI while the cross-validation estimate gives 0.9225. I need to check which value appears in Table 10 to resolve this. The text uses the cross-validation estimate of 0.9225 while the table uses the bootstrap estimate of 0.9224—a genuine inconsistency that needs flagging. The other values I'm checking (Qwen-7B and LLaMA-3.1-8B metrics) are matching correctly across the table, registry, and text. I'm noticing a discrepancy between the paper text and the tables — the text reports 0.9225 for LLaMA's 0v1 AUC, but Table 10 shows 0.9224. The registry has both values: 0.9225 from cross-validation and 0.9224 from bootstrap, so since the table uses bootstrap values, 0.9224 is the correct one to report. I should focus on compiling the full audit results for the tables rather than getting lost in every inline text verification. I'm tracking down where the 0.9225 value appears in the text — it shows up in line 49 and line 54, but the table uses the bootstrap estimate of 0.9224, so I need to update both instances to match the table's canonical value.

Now I'm compiling the full list of discrepancies: the major issue with Mistral-7B values across all depth pairs in Table 10 not matching any registry experiment, the minor LLaMA-8B inconsistency between text and table that needs fixing to 0.9224, and the OLMo registry mismatch where exp_002 differs from the paper but the paper aligns with exp_olmo1b_c.

For the fixes, I should correct the LLaMA text references from 0.9225 to 0.9224 since the registry confirms 0.9224 is correct, but for Mistral I need to flag the discrepancy rather than blindly change values without verification since neither registry experiment matches the paper values.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6aff20ef-4f5d-4b67-b1f2-8d24633fe5b5",
  "isSidechain": false,
  "requestId": "req_011CbKQ3geky49jfr8JKu2u5",
  "type": "assistant",
  "uuid": "1506e51d-04af-4a91-8a0f-344f3e4546d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqPhRXKSEhLJTb4DfiHeLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4395,
      "cache_read_input_tokens": 85970,
      "output_tokens": 5426,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4395,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 5426,
          "cache_read_input_tokens": 85970,
          "cache_creation_input_tokens": 4395,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4395
          },
          "type": "message"
        }
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

_source line 70 · 2026-05-23T11:11:55.139Z_

Now let me compile the full audit. Let me verify the LLaMA text vs table discrepancy I spotted, and also do a final check on inline text values.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1506e51d-04af-4a91-8a0f-344f3e4546d2",
  "isSidechain": false,
  "requestId": "req_011CbKQ3geky49jfr8JKu2u5",
  "type": "assistant",
  "uuid": "64e1502b-0f70-4611-8326-4e658193b105",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqPhRXKSEhLJTb4DfiHeLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4395,
      "cache_read_input_tokens": 85970,
      "output_tokens": 5426,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4395,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 5426,
          "cache_read_input_tokens": 85970,
          "cache_creation_input_tokens": 4395,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4395
          },
          "type": "message"
        }
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

_source line 71 · 2026-05-23T11:12:21.879Z_

<details open><summary>🔧 Tool call — Bash · `toolu_0135GTmDXyJgJQMWnSJKyJcy`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Full comparison table\nconfigs = {\n    'Qwen-rw': {\n        'reg_exp': 'exp_007_bootstrap_ci',\n        'reg_key': 'qwen_rewrite',\n        'paper_auc': {'0v1': .9956, '1v2': .6955, '2v3': .5893, '3v4': .5435, '4v5': .5340},\n        'paper_ci_1v2': [.686, .704],\n        'paper_ci_2v3': [.580, .599],\n    },\n    'Pythia': {\n        'reg_exp': 'exp_001_pythia_depth',\n        'paper_auc': {'0v1': .9722, '1v2': .6074, '2v3': .5440, '3v4': .5051, '4v5': .5079},\n        'paper_ci_1v2': [.598, .617],\n        'paper_ci_2v3': [.534, .554],\n    },\n    'OLMo': {\n        'reg_exp': 'exp_002_olmo_depth',\n        'paper_auc': {'0v1': .9860, '1v2': .5001, '2v3': .4973, '3v4': .5024, '4v5': .4942},\n        'paper_ci_1v2': [.496, .519],\n        'paper_ci_2v3': [.486, .509],\n    },\n    'Qwen-cont': {\n        'reg_exp': 'exp_007_bootstrap_ci',\n        'reg_key': 'qwen_cont',\n        'paper_auc': {'0v1': .9971, '1v2': .6112, '2v3': .5609, '3v4': .5409, '4v5': .5141},\n        'paper_ci_1v2': [.602, .621],\n        'paper_ci_2v3': [.551, .571],\n    },\n    'Qwen-7B': {\n        'reg_exp': 'exp_004_7b_crossscale',\n        'paper_auc': {'0v1': .9638, '1v2': .6168, '2v3': .5492, '3v4': .5276, '4v5': .5085},\n    },\n    'Qwen-base': {\n        'reg_exp': 'exp_016_base_vs_instruct',\n        'paper_auc': {'0v1': .987, '1v2': .626, '2v3': .550, '3v4': .529, '4v5': .518},\n    },\n    'LLaMA-8B': {\n        'reg_exp': 'exp_018_llama8b_depth',\n        'paper_auc': {'0v1': .9224, '1v2': .6123, '2v3': .5273, '3v4': .5168, '4v5': .5159},\n    },\n    'Mistral-7B': {\n        'reg_exp': 'exp_019b_mistral_cross_scorer',\n        'paper_auc': {'0v1': .9170, '1v2': .5750, '2v3': .5369, '3v4': .5174, '4v5': .5175},\n    },\n    'Pythia-6.9B': {\n        'reg_exp': 'exp_pythia69b_c4_nuc',\n        'paper_auc': {'0v1': .9599, '1v2': .5955, '2v3': .5298, '3v4': .5135},\n    },\n    'Gemma-2B': {\n        'reg_exp': 'exp_gemma2b_depth',\n        'paper_auc': {'0v1': .953, '1v2': .5981, '2v3': .534, '3v4': .5033, '4v5': .5025},\n    },\n}\n\nmismatches = []\nfor config_name, config in configs.items():\n    exp_id = config['reg_exp']\n    exp = exps.get(exp_id, {})\n    metrics = exp.get('metrics', {})\n    \n    # Get registry AUC values\n    reg_key = config.get('reg_key', None)\n    if reg_key:\n        reg_data = metrics.get(reg_key, {})\n        reg_auc = {dp: reg_data[dp]['auc'] for dp in reg_data if isinstance(reg_data.get(dp), dict) and 'auc' in reg_data.get(dp, {})}\n    else:\n        reg_auc = metrics.get('pairwise_auc', {})\n        if not reg_auc:\n            # Try bootstrap_ci format\n            ci_data = metrics.get('bootstrap_ci', {})\n            if ci_data and all(isinstance(v, dict) and 'auc' in v for v in ci_data.values()):\n                reg_auc = {dp: ci_data[dp]['auc'] for dp in ci_data}\n    \n    paper_auc = config['paper_auc']\n    \n    for dp in ['0v1', '1v2', '2v3', '3v4', '4v5']:\n        paper_val = paper_auc.get(dp, None)\n        reg_val = reg_auc.get(dp, None)\n        if paper_val is None:\n            continue\n        if reg_val is None:\n            mismatches.append((config_name, dp, paper_val, exp_id, 'MISSING', 'N/A'))\n            continue\n        \n        # Check match with tolerance for rounding\n        diff = abs(paper_val - reg_val)\n        if diff > 0.00015:  # Allow for 4th decimal rounding\n            match = 'MISMATCH'\n            mismatches.append((config_name, dp, paper_val, exp_id, reg_val, f'Δ={diff:.4f}'))\n        else:\n            pass  # match\n\nprint('=== MISMATCHES FOUND ===')\nprint(f'{'Config':<15} {'Pair':<6} {'Paper':<8} {'Exp ID':<35} {'Registry':<10} {'Note'}')\nprint('-' * 90)\nfor m in mismatches:\n    print(f'{m[0]:<15} {m[1]:<6} {m[2]:<8.4f} {m[3]:<35} {str(m[4]):<10} {m[5]}')\n\" 2>&1\n",
  "description": "Full systematic comparison of paper vs registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "64e1502b-0f70-4611-8326-4e658193b105",
  "isSidechain": false,
  "requestId": "req_011CbKQ3geky49jfr8JKu2u5",
  "type": "assistant",
  "uuid": "952e2ae8-2521-43e1-96b9-400390e579eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqPhRXKSEhLJTb4DfiHeLw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4395,
      "cache_read_input_tokens": 85970,
      "output_tokens": 5426,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4395,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 5426,
          "cache_read_input_tokens": 85970,
          "cache_creation_input_tokens": 4395,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4395
          },
          "type": "message"
        }
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

_source line 72 · 2026-05-23T11:12:21.989Z_

<details><summary>↩ Tool result · `toolu_0135GTmDXyJgJQMWnSJKyJcy`</summary>

```text
=== MISMATCHES FOUND ===
Config          Pair   Paper    Exp ID                              Registry   Note
------------------------------------------------------------------------------------------
OLMo            3v4    0.5024   exp_002_olmo_depth                  0.5034     Δ=0.0010
OLMo            4v5    0.4942   exp_002_olmo_depth                  0.4971     Δ=0.0029
Qwen-7B         0v1    0.9638   exp_004_7b_crossscale               0.9644     Δ=0.0006
Qwen-7B         1v2    0.6168   exp_004_7b_crossscale               0.6178     Δ=0.0010
Qwen-7B         2v3    0.5492   exp_004_7b_crossscale               0.546      Δ=0.0032
Qwen-7B         3v4    0.5276   exp_004_7b_crossscale               0.5225     Δ=0.0051
Qwen-7B         4v5    0.5085   exp_004_7b_crossscale               0.5091     Δ=0.0006
Qwen-base       1v2    0.6260   exp_016_base_vs_instruct            0.6262     Δ=0.0002
Qwen-base       2v3    0.5500   exp_016_base_vs_instruct            0.5496     Δ=0.0004
Qwen-base       3v4    0.5290   exp_016_base_vs_instruct            0.5294     Δ=0.0004
Qwen-base       4v5    0.5180   exp_016_base_vs_instruct            0.5182     Δ=0.0002
LLaMA-8B        3v4    0.5168   exp_018_llama8b_depth               0.5138     Δ=0.0030
LLaMA-8B        4v5    0.5159   exp_018_llama8b_depth               0.5097     Δ=0.0062
Mistral-7B      0v1    0.9170   exp_019b_mistral_cross_scorer       0.9209     Δ=0.0039
Mistral-7B      1v2    0.5750   exp_019b_mistral_cross_scorer       0.5695     Δ=0.0055
Mistral-7B      2v3    0.5369   exp_019b_mistral_cross_scorer       0.5335     Δ=0.0034
Mistral-7B      3v4    0.5174   exp_019b_mistral_cross_scorer       0.514      Δ=0.0034
Mistral-7B      4v5    0.5175   exp_019b_mistral_cross_scorer       0.5184     Δ=0.0009
Gemma-2B        0v1    0.9530   exp_gemma2b_depth                   0.9534     Δ=0.0004
Gemma-2B        2v3    0.5340   exp_gemma2b_depth                   0.5342     Δ=0.0002
Gemma-2B        3v4    0.5033   exp_gemma2b_depth                   0.503      Δ=0.0003
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "952e2ae8-2521-43e1-96b9-400390e579eb",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "ab694633-61e5-4430-ba8a-a8bbde82a3dd",
  "toolUseResult": {
    "stdout": "=== MISMATCHES FOUND ===\nConfig          Pair   Paper    Exp ID                              Registry   Note\n------------------------------------------------------------------------------------------\nOLMo            3v4    0.5024   exp_002_olmo_depth                  0.5034     Δ=0.0010\nOLMo            4v5    0.4942   exp_002_olmo_depth                  0.4971     Δ=0.0029\nQwen-7B         0v1    0.9638   exp_004_7b_crossscale               0.9644     Δ=0.0006\nQwen-7B         1v2    0.6168   exp_004_7b_crossscale               0.6178     Δ=0.0010\nQwen-7B         2v3    0.5492   exp_004_7b_crossscale               0.546      Δ=0.0032\nQwen-7B         3v4    0.5276   exp_004_7b_crossscale               0.5225     Δ=0.0051\nQwen-7B         4v5    0.5085   exp_004_7b_crossscale               0.5091     Δ=0.0006\nQwen-base       1v2    0.6260   exp_016_base_vs_instruct            0.6262     Δ=0.0002\nQwen-base       2v3    0.5500   exp_016_base_vs_instruct            0.5496     Δ=0.0004\nQwen-base       3v4    0.5290   exp_016_base_vs_instruct            0.5294     Δ=0.0004\nQwen-base       4v5    0.5180   exp_016_base_vs_instruct            0.5182     Δ=0.0002\nLLaMA-8B        3v4    0.5168   exp_018_llama8b_depth               0.5138     Δ=0.0030\nLLaMA-8B        4v5    0.5159   exp_018_llama8b_depth               0.5097     Δ=0.0062\nMistral-7B      0v1    0.9170   exp_019b_mistral_cross_scorer       0.9209     Δ=0.0039\nMistral-7B      1v2    0.5750   exp_019b_mistral_cross_scorer       0.5695     Δ=0.0055\nMistral-7B      2v3    0.5369   exp_019b_mistral_cross_scorer       0.5335     Δ=0.0034\nMistral-7B      3v4    0.5174   exp_019b_mistral_cross_scorer       0.514      Δ=0.0034\nMistral-7B      4v5    0.5175   exp_019b_mistral_cross_scorer       0.5184     Δ=0.0009\nGemma-2B        0v1    0.9530   exp_gemma2b_depth                   0.9534     Δ=0.0004\nGemma-2B        2v3    0.5340   exp_gemma2b_depth                   0.5342     Δ=0.0002\nGemma-2B        3v4    0.5033   exp_gemma2b_depth                   0.503      Δ=0.0003",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "952e2ae8-2521-43e1-96b9-400390e579eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 73_

```json
{
  "type": "last-prompt",
  "leafUuid": "ab694633-61e5-4430-ba8a-a8bbde82a3dd",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 74_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Assistant

_source line 75 · 2026-05-23T11:12:46.813Z_

<details><summary>Logged reasoning block</summary>

````text
Now I see the full picture. Let me categorize the mismatches:

**exp_004_7b_crossscale (Qwen-7B)**: The paper uses bootstrap_ci values, not pairwise_auc values. Let me verify this. The registry has both pairwise_auc (CV estimates) and bootstrap_ci (bootstrap estimates). The paper's Table 2/10 values for Qwen-7B match the bootstrap_ci values, not the pairwise_auc. Let me verify by checking the bootstrap_ci values for exp_004.

From earlier:
```
bootstrap_ci: {'0v1': {'auc': 0.9638, ...}, '1v2': {'auc': 0.6168, ...}, '2v3': {'auc': 0.5492, ...}, '3v4': {'auc': 0.5276, ...}, '4v5': {'auc': 0.5085, ...}}


```

The paper values for Qwen-7B match the bootstrap_ci AUC values exactly — the script was comparing against pairwise_auc instead of bootstrap_ci, so this isn't a real mismatch. For LLaMA-8B, I should verify the same thing by checking if the paper values align with bootstrap_ci estimates rather than the cross-validation estimates.

Looking at the bootstrap_ci values for LLaMA-8B, the paper's reported AUC scores of .9224, .6123, .5273, .5168, and .5159 match perfectly with the bootstrap point estimates. This confirms the pattern — the paper correctly uses bootstrap estimates, not pairwise comparisons. The same holds for Qwen-base, where I'm checking if the bootstrap_ci values align with what the paper reports.

```
bootstrap_ci: {0v1: {auc: 0.987}, 1v2: {auc: 0.626}, 2v3: {auc: 0.5496}, 3v4: {auc: 0.5293}, 4v5: {auc: 0.5181}}
```

The paper shows .987, .626, .550, .529, .518 — these are just the bootstrap values rounded to three decimal places. For Gemma-2B, the same pattern holds: .953 rounds from 0.9534, and .534 rounds from 0.5342. These aren't mismatches at all, just standard rounding for presentation.

After filtering out the rounding artifacts and the bootstrap_ci versus pairwise_auc differences, I'm left with three genuine discrepancies: OLMo's 3v4 and 4v5 pairs show small differences between the paper and the registry that suggest the registry values need updating, while Mistral-7B's values don't align with any of the experimental runs I've checked.

There's also a potential text-table inconsistency with LLaMA-8B's 0v1 result where the narrative mentions 0.9225 but the table shows .9224. Let me verify this LLaMA discrepancy and then compile the final report, using the bootstrap_ci values as my reference point for the comparison.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ab694633-61e5-4430-ba8a-a8bbde82a3dd",
  "isSidechain": false,
  "requestId": "req_011CbKQBy5T7Xz6wSccAMghs",
  "type": "assistant",
  "uuid": "0ea9d88f-bc44-4660-b79e-501b8ca29247",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U44e7rHT852m1jnZwM9T7K",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6314,
      "cache_read_input_tokens": 90365,
      "output_tokens": 2905,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6314,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2905,
          "cache_read_input_tokens": 90365,
          "cache_creation_input_tokens": 6314,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6314
          },
          "type": "message"
        }
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

_source line 76 · 2026-05-23T11:12:46.928Z_

The Qwen-7B, LLaMA-8B, and Qwen-base "mismatches" are comparing pairwise_auc (CV estimates) instead of bootstrap_ci (bootstrap estimates). Let me redo with the correct source.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0ea9d88f-bc44-4660-b79e-501b8ca29247",
  "isSidechain": false,
  "requestId": "req_011CbKQBy5T7Xz6wSccAMghs",
  "type": "assistant",
  "uuid": "a6e2aeec-3803-43d7-b00b-1acdfaa3790d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U44e7rHT852m1jnZwM9T7K",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6314,
      "cache_read_input_tokens": 90365,
      "output_tokens": 2905,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6314,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2905,
          "cache_read_input_tokens": 90365,
          "cache_creation_input_tokens": 6314,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6314
          },
          "type": "message"
        }
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

_source line 77 · 2026-05-23T11:13:09.192Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01CP9KckLgGSWs2VyprZdfA7`</summary>

```json
{
  "command": "REGFILE=\"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-7-projects-gen-depth-contamination/34d999f9-ba08-4dc3-8d75-ac2750aed5c6/tool-results/mcp-agent-ml-research-read_registry-1779534109586.txt\"\ncat \"$REGFILE\" | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\ndef get_auc_from_exp(exp_id, reg_key=None):\n    exp = exps.get(exp_id, {})\n    metrics = exp.get('metrics', {})\n    \n    if reg_key:\n        reg_data = metrics.get(reg_key, {})\n        return {dp: reg_data[dp]['auc'] for dp in reg_data if isinstance(reg_data.get(dp), dict) and 'auc' in reg_data.get(dp, {})}\n    \n    # Prefer bootstrap_ci (point estimates from bootstrap)\n    ci_data = metrics.get('bootstrap_ci', {})\n    if ci_data:\n        auc_dict = {}\n        for dp, val in ci_data.items():\n            if isinstance(val, dict) and 'auc' in val:\n                auc_dict[dp] = val['auc']\n            elif isinstance(val, dict) and 'mean' in val:\n                auc_dict[dp] = val['mean']\n        if auc_dict:\n            return auc_dict\n    \n    # Fall back to pairwise_auc\n    return metrics.get('pairwise_auc', {})\n\nconfigs = {\n    'Qwen-rw': ('exp_007_bootstrap_ci', 'qwen_rewrite', \n        {'0v1': .9956, '1v2': .6955, '2v3': .5893, '3v4': .5435, '4v5': .5340}),\n    'Pythia': ('exp_001_pythia_depth', None,\n        {'0v1': .9722, '1v2': .6074, '2v3': .5440, '3v4': .5051, '4v5': .5079}),\n    'OLMo': ('exp_002_olmo_depth', None,\n        {'0v1': .9860, '1v2': .5001, '2v3': .4973, '3v4': .5024, '4v5': .4942}),\n    'Qwen-cont': ('exp_007_bootstrap_ci', 'qwen_cont',\n        {'0v1': .9971, '1v2': .6112, '2v3': .5609, '3v4': .5409, '4v5': .5141}),\n    'Qwen-7B': ('exp_004_7b_crossscale', None,\n        {'0v1': .9638, '1v2': .6168, '2v3': .5492, '3v4': .5276, '4v5': .5085}),\n    'Qwen-base': ('exp_016_base_vs_instruct', None,\n        {'0v1': .987, '1v2': .626, '2v3': .550, '3v4': .529, '4v5': .518}),\n    'LLaMA-8B': ('exp_018_llama8b_depth', None,\n        {'0v1': .9224, '1v2': .6123, '2v3': .5273, '3v4': .5168, '4v5': .5159}),\n    'Mistral-7B': ('exp_019b_mistral_cross_scorer', None,\n        {'0v1': .9170, '1v2': .5750, '2v3': .5369, '3v4': .5174, '4v5': .5175}),\n    'Pythia-6.9B': ('exp_pythia69b_c4_nuc', None,\n        {'0v1': .9599, '1v2': .5955, '2v3': .5298, '3v4': .5135}),\n    'Gemma-2B': ('exp_gemma2b_depth', None,\n        {'0v1': .953, '1v2': .5981, '2v3': .534, '3v4': .5033, '4v5': .5025}),\n}\n\nmismatches = []\nfor config_name, (exp_id, reg_key, paper_auc) in configs.items():\n    reg_auc = get_auc_from_exp(exp_id, reg_key)\n    \n    # Determine decimal places from paper values\n    for dp in ['0v1', '1v2', '2v3', '3v4', '4v5']:\n        pv = paper_auc.get(dp)\n        rv = reg_auc.get(dp)\n        if pv is None:\n            continue\n        if rv is None:\n            mismatches.append((config_name, dp, f'{pv:.4f}', exp_id, 'MISSING', ''))\n            continue\n        \n        # Determine paper precision (number of significant decimals)\n        ps = f'{pv:.4f}'.rstrip('0')\n        ndp = len(ps.split('.')[1]) if '.' in ps else 0\n        ndp = max(ndp, 3)\n        \n        # Round registry to same precision for comparison\n        rv_rounded = round(rv, ndp)\n        pv_rounded = round(pv, ndp)\n        \n        if abs(pv_rounded - rv_rounded) > 1e-10:\n            diff = abs(pv - rv)\n            mismatches.append((config_name, dp, f'{pv:.4f}', exp_id, f'{rv:.4f}', f'Δ={diff:.4f}'))\n\nif mismatches:\n    print(f'{\\\"Config\\\":<15} {\\\"Pair\\\":<6} {\\\"Paper\\\":<8} {\\\"Exp ID\\\":<35} {\\\"Registry\\\":<10} {\\\"Note\\\"}')\n    print('-' * 90)\n    for m in mismatches:\n        print(f'{m[0]:<15} {m[1]:<6} {m[2]:<8} {m[3]:<35} {m[4]:<10} {m[5]}')\nelse:\n    print('No mismatches found')\n\" 2>&1\n",
  "description": "Re-run comparison with bootstrap estimates"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a6e2aeec-3803-43d7-b00b-1acdfaa3790d",
  "isSidechain": false,
  "requestId": "req_011CbKQBy5T7Xz6wSccAMghs",
  "type": "assistant",
  "uuid": "510191c0-5eb6-4e2b-bf96-593c3de5a37d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U44e7rHT852m1jnZwM9T7K",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6314,
      "cache_read_input_tokens": 90365,
      "output_tokens": 2905,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6314,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2905,
          "cache_read_input_tokens": 90365,
          "cache_creation_input_tokens": 6314,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6314
          },
          "type": "message"
        }
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

_source line 78 · 2026-05-23T11:13:09.331Z_

<details><summary>↩ Tool result · `toolu_01CP9KckLgGSWs2VyprZdfA7`</summary>

```text
Config          Pair   Paper    Exp ID                              Registry   Note
------------------------------------------------------------------------------------------
OLMo            2v3    0.4973   exp_002_olmo_depth                  0.4972     Δ=0.0001
OLMo            3v4    0.5024   exp_002_olmo_depth                  0.5034     Δ=0.0010
OLMo            4v5    0.4942   exp_002_olmo_depth                  0.4971     Δ=0.0029
Mistral-7B      0v1    0.9170   exp_019b_mistral_cross_scorer       0.9209     Δ=0.0039
Mistral-7B      1v2    0.5750   exp_019b_mistral_cross_scorer       0.5696     Δ=0.0054
Mistral-7B      2v3    0.5369   exp_019b_mistral_cross_scorer       0.5335     Δ=0.0034
Mistral-7B      3v4    0.5174   exp_019b_mistral_cross_scorer       0.5140     Δ=0.0034
Mistral-7B      4v5    0.5175   exp_019b_mistral_cross_scorer       0.5183     Δ=0.0008
Gemma-2B        3v4    0.5033   exp_gemma2b_depth                   0.5030     Δ=0.0003
Gemma-2B        4v5    0.5025   exp_gemma2b_depth                   0.5026     Δ=0.0001
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "510191c0-5eb6-4e2b-bf96-593c3de5a37d",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "0e93dcf4-fd18-4a08-85c8-a1ef1f3991b1",
  "toolUseResult": {
    "stdout": "Config          Pair   Paper    Exp ID                              Registry   Note\n------------------------------------------------------------------------------------------\nOLMo            2v3    0.4973   exp_002_olmo_depth                  0.4972     Δ=0.0001\nOLMo            3v4    0.5024   exp_002_olmo_depth                  0.5034     Δ=0.0010\nOLMo            4v5    0.4942   exp_002_olmo_depth                  0.4971     Δ=0.0029\nMistral-7B      0v1    0.9170   exp_019b_mistral_cross_scorer       0.9209     Δ=0.0039\nMistral-7B      1v2    0.5750   exp_019b_mistral_cross_scorer       0.5696     Δ=0.0054\nMistral-7B      2v3    0.5369   exp_019b_mistral_cross_scorer       0.5335     Δ=0.0034\nMistral-7B      3v4    0.5174   exp_019b_mistral_cross_scorer       0.5140     Δ=0.0034\nMistral-7B      4v5    0.5175   exp_019b_mistral_cross_scorer       0.5183     Δ=0.0008\nGemma-2B        3v4    0.5033   exp_gemma2b_depth                   0.5030     Δ=0.0003\nGemma-2B        4v5    0.5025   exp_gemma2b_depth                   0.5026     Δ=0.0001",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "510191c0-5eb6-4e2b-bf96-593c3de5a37d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 79 · 2026-05-23T11:13:51.333Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture of the real mismatches. Let me categorize:

**Category 1: Registry stale (OLMo) — Paper is correct, registry needs update**
- OLMo 2v3: paper .4973, exp_002 0.4972 (tiny, matches rerun 0.4973)
- OLMo 3v4: paper .5024, exp_002 0.5034 (matches rerun 0.5024)
- OLMo 4v5: paper .4942, exp_002 0.4971 (matches rerun 0.4942)


- Mistral-7B shows a different pattern — none of the five depth pairs align with the registry experiment, with discrepancies ranging from 0.0008 to 0.0054, which I can't easily resolve.
- Gemma-2B falls within rounding error, with differences of 0.0003 and 0.0001 across the depth pairs.

Now I'm checking the text-table...

There's a discrepancy in the LLaMA-8B values: the paper text reports 0.9225 for the 0v1 AUC, but Table 10 shows 0.9224, which matches the bootstrap confidence interval in the registry rather than the cross-validation estimate. I need to decide whether the text should be corrected to match the table's bootstrap value or if using the CV estimate was intentional. I'm realizing the inconsistency is more significant than just rounding—0.9225 and 0.9224 round to different values at three decimal places (0.923 vs 0.922), so this needs to be corrected to match the table's authoritative value of 0.9224. I need to correct my table analysis—Mistral only appears in Table 10, not Table 2. Looking at the registry experiments for Mistral's values in Table 10, I'm trying to find which experiment matches the paper's reported numbers, but the closest match isn't exact.

The paper shows 0v1=.9170, 1v2=.5750, 2v3=.5369, 3v4=.5174, 4v5=.5175, while the registry experiment has slightly different values with a maximum difference of 0.005 across all pairs. Since I can't determine whether the paper ran an unregistered experiment or if there's a discrepancy, I should flag this for the user rather than override it. For the OLMo issue, I'm checking if the paper's values for 3v4 and 4v5 match the registry experiment.

The paper values align with the OLMo rerun, not the stale registry entry, so the paper is correct and no fix is needed there. For Gemma, the differences are tiny (0.0003 and 0.0001), likely just precision artifacts from registry storage, so those don't warrant correction. Now I'm ready to make the text fixes for LLaMA and compile the full audit report, though I should also scan the paper for any other inline numerical values that need verification.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0e93dcf4-fd18-4a08-85c8-a1ef1f3991b1",
  "isSidechain": false,
  "requestId": "req_011CbKQFTHRevDiMhrXPG1HB",
  "type": "assistant",
  "uuid": "5a6095e6-bed8-4198-9847-d4d632d17b84",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UDfCYR9N83M7LdBCmQG6KG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3338,
      "cache_read_input_tokens": 96679,
      "output_tokens": 1889,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3338,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1889,
          "cache_read_input_tokens": 96679,
          "cache_creation_input_tokens": 3338,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3338
          },
          "type": "message"
        }
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

_source line 80 · 2026-05-23T11:13:51.334Z_

Now let me check the text-table inconsistency for LLaMA-8B 0v1.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5a6095e6-bed8-4198-9847-d4d632d17b84",
  "isSidechain": false,
  "requestId": "req_011CbKQFTHRevDiMhrXPG1HB",
  "type": "assistant",
  "uuid": "cc68f247-afaf-478a-8149-0859de200ec9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UDfCYR9N83M7LdBCmQG6KG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3338,
      "cache_read_input_tokens": 96679,
      "output_tokens": 1889,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3338,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1889,
          "cache_read_input_tokens": 96679,
          "cache_creation_input_tokens": 3338,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3338
          },
          "type": "message"
        }
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

_source line 81 · 2026-05-23T11:13:52.298Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01XsGAVL7fJyo3CzAkP3eGXp`</summary>

```json
{
  "pattern": "0\\.9225",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cc68f247-afaf-478a-8149-0859de200ec9",
  "isSidechain": false,
  "requestId": "req_011CbKQFTHRevDiMhrXPG1HB",
  "type": "assistant",
  "uuid": "1e9d86e7-7f4f-4168-8e65-b0d51020f170",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UDfCYR9N83M7LdBCmQG6KG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3338,
      "cache_read_input_tokens": 96679,
      "output_tokens": 1889,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3338,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1889,
          "cache_read_input_tokens": 96679,
          "cache_creation_input_tokens": 3338,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3338
          },
          "type": "message"
        }
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

_source line 82 · 2026-05-23T11:13:52.319Z_

<details><summary>↩ Tool result · `toolu_01XsGAVL7fJyo3CzAkP3eGXp`</summary>

```text
docs/paper/appendix_extended.tex:50:Cross-scale validation confirms $\Kempirical = 2$ from 1.5B through 8B: Qwen-7B (1v2 $\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\auc = 0.6123$, 0v1 $= 0.9225$) both exceed $\theta$, with progressively lower 0v1 signal consistent with larger models generating more human-like text.
docs/paper/experiments_c1.tex:49:LLaMA-3.1-8B confirms $\Kempirical{=}2$ (0v1 $\auc = 0.9225$, 1v2 $\auc = 0.6123\;[0.603,\,0.622]$; CI lower bound above $\theta$; Table~\ref{tab:kstar_ci_extended}).
docs/paper/experiments_c1.tex:54:$\Kempirical{=}2$ persists from 1.5B through 8B: Qwen-7B (1v2 $\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\auc = 0.6123$) both exceed $\theta$, despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\ $> 0.99$ at $\leq$1.5B).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1e9d86e7-7f4f-4168-8e65-b0d51020f170",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "f6552455-42e0-48f6-9ab5-a39d40215e84",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/appendix_extended.tex:50:Cross-scale validation confirms $\\Kempirical = 2$ from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9225$) both exceed $\\theta$, with progressively lower 0v1 signal consistent with larger models generating more human-like text.\ndocs/paper/experiments_c1.tex:49:LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9225$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).\ndocs/paper/experiments_c1.tex:54:$\\Kempirical{=}2$ persists from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$) both exceed $\\theta$, despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\\ $> 0.99$ at $\\leq$1.5B).",
    "numLines": 3
  },
  "sourceToolAssistantUUID": "1e9d86e7-7f4f-4168-8e65-b0d51020f170",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 83 · 2026-05-23T11:14:07.544Z_

<details><summary>Logged reasoning block</summary>

```text
Three occurrences of 0.9225:
1. experiments_c1.tex line 49
2. experiments_c1.tex line 54
3. appendix_extended.tex line 50

Table 10 says .9224. Registry bootstrap_ci says 0.9224. The text has 0.9225 (CV estimate). These should all say 0.9224 to match the table.

But wait — is .9224 or .9225 the "correct" value? The pairwise_auc (cross-validation average) is 0.9225. 

The bootstrap point estimate is 0.9224, which is what typically gets reported in tables alongside confidence intervals. So the table value .9224 is correct, and I need to update the text to match. Let me verify that Table 10's .9224 is actually correct by checking it against the registry values for LLaMA-8B 0v1.

Looking at the registry, the bootstrap_ci for 0v1 shows auc=0.9224 with ci_lower=0.9174 and ci_upper=0.9272. The table displays [.917, .927], which is the correct rounding of [0.9174, 0.9272]. So the table value is accurate.

Now I need to fix the three instances where 0.9225 appears in the text—they should all be 0.9224 to match the bootstrap estimate. But let me double-check the registry first: the pairwise_auc shows 0.9225 (which is the mean across cross-validation), while the bootstrap_ci shows 0.9224 as the actual point estimate. Since the table uses the bootstrap estimate, I should correct those text references to 0.9224.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f6552455-42e0-48f6-9ab5-a39d40215e84",
  "isSidechain": false,
  "requestId": "req_011CbKQJd6rgz3cqME3ffFpk",
  "type": "assistant",
  "uuid": "8f7670fb-e875-4fc9-bc1e-b18130ed947d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BKzyVjbmnqMoLWwYmDo7tX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2303,
      "cache_read_input_tokens": 100017,
      "output_tokens": 2114,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2303,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2114,
          "cache_read_input_tokens": 100017,
          "cache_creation_input_tokens": 2303,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2303
          },
          "type": "message"
        }
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

_source line 84 · 2026-05-23T11:14:27.284Z_

Found 3 occurrences of 0.9225 in text, but Table 10 has .9224 (bootstrap estimate). Let me now compile the complete audit and make fixes.

## Full Audit Results

### Table 1 (method.tex, tab:setup)
All 6 configurations correct: model names and parameter counts match.

### Table 2 vs Table 10 consistency
All 5 overlapping configs (Qwen-rw, Pythia, OLMo, Qwen-cont, Qwen-7B) are **perfectly consistent** between tables.

### Table 2 + Table 10 vs Registry

| Config | Pair | Paper | Registry exp_id | Registry | Match |
|--------|------|-------|-----------------|----------|-------|
| Qwen-rw | all 5 | ✓ | exp_007_bootstrap_ci | ✓ | ✓ |
| Pythia | all 5 | ✓ | exp_001_pythia_depth | ✓ | ✓ |
| Qwen-cont | all 5 | ✓ | exp_007_bootstrap_ci | ✓ | ✓ |
| Qwen-7B | all 5 | ✓ | exp_004_7b_crossscale (bootstrap) | ✓ | ✓ |
| Qwen-base | all 5 | ✓ | exp_016_base_vs_instruct (bootstrap) | ✓ | ✓ |
| LLaMA-8B | all 5 | ✓ | exp_018_llama8b_depth (bootstrap) | ✓ | ✓ |
| Pythia-6.9B | all 4 | ✓ | exp_pythia69b_c4_nuc | ✓ | ✓ |
| **OLMo** | **3v4** | **.5024** | exp_002_olmo_depth | **0.5034** | **❌** |
| **OLMo** | **4v5** | **.4942** | exp_002_olmo_depth | **0.4971** | **❌** |
| **Mistral-7B** | **0v1** | **.9170** | exp_019b_mistral_cross_scorer | **0.9209** | **❌** |
| **Mistral-7B** | **1v2** | **.5750** | exp_019b_mistral_cross_scorer | **0.5696** | **❌** |
| **Mistral-7B** | **2v3** | **.5369** | exp_019b_mistral_cross_scorer | **0.5335** | **❌** |
| **Mistral-7B** | **3v4** | **.5174** | exp_019b_mistral_cross_scorer | **0.5140** | **❌** |
| **Mistral-7B** | **4v5** | **.5175** | exp_019b_mistral_cross_scorer | **0.5184** | **❌** |
| Gemma-2B | 3v4 | .5033 | exp_gemma2b_depth | 0.503 | ~(Δ=.0003) |
| Gemma-2B | 4v5 | .5025 | exp_gemma2b_depth | 0.5026 | ~(Δ=.0001) |

### Analysis

1. **OLMo 3v4/4v5**: Paper values (.5024, .4942) match `exp_olmo1b_c4_rerun`, not `exp_002_olmo_depth`. The registry entry `exp_002` is stale — **paper is correct, registry needs update**. No paper fix needed.

2. **Mistral-7B (ALL 5 values)**: Paper values don't match ANY registered experiment. Neither `exp_019` (self-scored: 0v1=.9843) nor `exp_019b` (cross-scored: 0v1=.9209) matches the paper (0v1=.9170). This suggests the paper uses an unregistered run. **Cannot fix without source data — flagging for manual verification.**

3. **Gemma-2B 3v4/4v5**: Δ ≤ 0.0003, likely registry storage precision. Negligible.

4. **Text-table inconsistency**: LLaMA-8B 0v1 is `0.9225` in body text (3 occurrences) but `.9224` in Table 10. Table uses bootstrap point estimate (matches registry `exp_018` bootstrap_ci: 0.9224). Text uses CV estimate (0.9225). **Fixing text to match table.**

Now fixing the LLaMA text inconsistency:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8f7670fb-e875-4fc9-bc1e-b18130ed947d",
  "isSidechain": false,
  "requestId": "req_011CbKQJd6rgz3cqME3ffFpk",
  "type": "assistant",
  "uuid": "8bd50dbd-38ed-46f2-8118-3bd26a16ad8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BKzyVjbmnqMoLWwYmDo7tX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2303,
      "cache_read_input_tokens": 100017,
      "output_tokens": 2114,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2303,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2114,
          "cache_read_input_tokens": 100017,
          "cache_creation_input_tokens": 2303,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2303
          },
          "type": "message"
        }
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

_source line 85 · 2026-05-23T11:14:29.322Z_

<details open><summary>🔧 Tool call — Edit · `toolu_011e4PKS7dzb9TYSMfiUhrBn`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
  "old_string": "LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9225$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).",
  "new_string": "LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9224$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8bd50dbd-38ed-46f2-8118-3bd26a16ad8e",
  "isSidechain": false,
  "requestId": "req_011CbKQJd6rgz3cqME3ffFpk",
  "type": "assistant",
  "uuid": "d9b8dec2-a0b5-49ef-95d9-fa6a18a7db26",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BKzyVjbmnqMoLWwYmDo7tX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2303,
      "cache_read_input_tokens": 100017,
      "output_tokens": 2114,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2303,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2114,
          "cache_read_input_tokens": 100017,
          "cache_creation_input_tokens": 2303,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2303
          },
          "type": "message"
        }
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

_source line 86 · 2026-05-23T11:14:29.346Z_

<details><summary>↩ Tool result · `toolu_011e4PKS7dzb9TYSMfiUhrBn`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d9b8dec2-a0b5-49ef-95d9-fa6a18a7db26",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "49c1f853-ec1c-4216-9172-d035dd795d41",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
    "oldString": "LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9225$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).",
    "newString": "LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9224$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).",
    "originalFile": null,
    "structuredPatch": [
      {
        "oldStart": 46,
        "oldLines": 7,
        "newStart": 46,
        "newLines": 7,
        "lines": [
          " Table~\\ref{tab:kstar_ci} and Figure~\\ref{fig:auc_decay} show $\\Kempirical \\leq 2$ across all 10 configurations: 6/10 yield $\\Kempirical{=}2$ (Qwen$\\times$4, LLaMA-8B, Pythia-1.4B; 1v2 $\\auc$: 0.607--0.696; $p < 0.001$), while OLMo-1B, Mistral-7B, Pythia-6.9B, and Gemma-2-2B yield $\\Kempirical{=}1$ (1v2 $\\auc$: 0.500--0.598; Section~\\ref{sec:boundary_cases}).",
          " Under Bonferroni correction (99.5\\% CIs), three of six $\\Kempirical{=}2$ configurations retain significance; the three marginal cases (Pythia-1.4B, Qwen-cont, LLaMA-8B; CI lower bounds 0.593--0.599) reflect narrow effect sizes rather than classification failure.",
          " By architecture family: Qwen (4/4) and LLaMA (1/1) yield $\\Kempirical{\\geq}2$ at nominal significance; OLMo (1/1), Mistral (1/1), and Gemma (1/1) yield $\\Kempirical{=}1$; Pythia exhibits a scale-dependent split (1.4B: $\\Kempirical{=}2$, 6.9B: $\\Kempirical{=}1$).",
          "-LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9225$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).",
          "+LLaMA-3.1-8B confirms $\\Kempirical{=}2$ (0v1 $\\auc = 0.9224$, 1v2 $\\auc = 0.6123\\;[0.603,\\,0.622]$; CI lower bound above $\\theta$; Table~\\ref{tab:kstar_ci_extended}).",
          " All four decoding strategies likewise yield $\\Kempirical{=}2$ (Table~\\ref{tab:s2_decoding}).",
          " The 1v2 spread due to generation mode ($\\Delta = 8.4$\\,pp within Qwen) exceeds the spread across $\\Kempirical{=}2$ continuation models ($\\Delta = 1.9$\\,pp).",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "d9b8dec2-a0b5-49ef-95d9-fa6a18a7db26",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
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
  "type": "last-prompt",
  "leafUuid": "49c1f853-ec1c-4216-9172-d035dd795d41",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 88_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Tool call

_source line 89 · 2026-05-23T11:14:38.227Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01HyTZZenSKzr48haLC42mpW`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
  "old_string": "despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\\ $> 0.99$ at $\\leq$1.5B).",
  "new_string": "despite progressively reduced 0v1 signal (0.9638 and 0.9224 vs.\\ $> 0.99$ at $\\leq$1.5B)."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "49c1f853-ec1c-4216-9172-d035dd795d41",
  "isSidechain": false,
  "requestId": "req_011CbKQMMgVudhFohR6JAVNS",
  "type": "assistant",
  "uuid": "38b4f11e-24fa-4417-8cea-39b5dea181a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GNS4yVNY31MUAyUC7ZnNRm",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2189,
      "cache_read_input_tokens": 102320,
      "output_tokens": 234,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2189,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 234,
          "cache_read_input_tokens": 102320,
          "cache_creation_input_tokens": 2189,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2189
          },
          "type": "message"
        }
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

_source line 90 · 2026-05-23T11:14:38.243Z_

<details><summary>↩ Tool result · `toolu_01HyTZZenSKzr48haLC42mpW`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "38b4f11e-24fa-4417-8cea-39b5dea181a4",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "57833e95-613a-440a-ae37-f804e3d0a831",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex",
    "oldString": "despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\\ $> 0.99$ at $\\leq$1.5B).",
    "newString": "despite progressively reduced 0v1 signal (0.9638 and 0.9224 vs.\\ $> 0.99$ at $\\leq$1.5B).",
    "originalFile": null,
    "structuredPatch": [
      {
        "oldStart": 51,
        "oldLines": 7,
        "newStart": 51,
        "newLines": 7,
        "lines": [
          " The 1v2 spread due to generation mode ($\\Delta = 8.4$\\,pp within Qwen) exceeds the spread across $\\Kempirical{=}2$ continuation models ($\\Delta = 1.9$\\,pp).",
          " ",
          " \\paragraph{Scale and instruction-tuning invariance.}",
          "-$\\Kempirical{=}2$ persists from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$) both exceed $\\theta$, despite progressively reduced 0v1 signal (0.9638 and 0.9225 vs.\\ $> 0.99$ at $\\leq$1.5B).",
          "+$\\Kempirical{=}2$ persists from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$) both exceed $\\theta$, despite progressively reduced 0v1 signal (0.9638 and 0.9224 vs.\\ $> 0.99$ at $\\leq$1.5B).",
          " A base-vs.-instruct ablation at 1.5B likewise yields $\\Kempirical = 2$ (1v2 $\\auc = 0.626$), confirming the boundary is not an instruction-tuning artifact.",
          " ",
          " \\begin{figure*}[t]"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "38b4f11e-24fa-4417-8cea-39b5dea181a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 91 · 2026-05-23T11:14:41.415Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Uep56j9KBD8LVqboNyX7fL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
  "offset": 48,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "57833e95-613a-440a-ae37-f804e3d0a831",
  "isSidechain": false,
  "requestId": "req_011CbKQN1TrJ57k5yDykTQay",
  "type": "assistant",
  "uuid": "3c5194ab-e430-4500-a2be-2930f07e0c20",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UgTq7NQEnhppT7MYCjGaRn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 291,
      "cache_read_input_tokens": 104509,
      "output_tokens": 125,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 291,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 125,
          "cache_read_input_tokens": 104509,
          "cache_creation_input_tokens": 291,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 291
          },
          "type": "message"
        }
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

_source line 92 · 2026-05-23T11:14:41.420Z_

<details><summary>↩ Tool result · `toolu_01Uep56j9KBD8LVqboNyX7fL`</summary>

```text
48	\label{sec:extended_neural_probe}
49	
50	Cross-scale validation confirms $\Kempirical = 2$ from 1.5B through 8B: Qwen-7B (1v2 $\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\auc = 0.6123$, 0v1 $= 0.9225$) both exceed $\theta$, with progressively lower 0v1 signal consistent with larger models generating more human-like text.
51	Gemma-2-27B (C4 continuation, Qwen cross-scored) yields $\Kempirical{=}1$ (1v2 $\auc = 0.5894$), consistent with Gemma-2-2B at 5K ($\Kempirical{=}1$, 1v2 $\auc = 0.5981$). The Gemma family produces $\Kempirical{=}1$ at both 2B and 27B, suggesting $\Kempirical$ is model-family-dependent rather than scale-dependent.
52	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3c5194ab-e430-4500-a2be-2930f07e0c20",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "87b20e5d-0ee6-4d5b-a46b-c365c4694265",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
      "content": "\\label{sec:extended_neural_probe}\n\nCross-scale validation confirms $\\Kempirical = 2$ from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9225$) both exceed $\\theta$, with progressively lower 0v1 signal consistent with larger models generating more human-like text.\nGemma-2-27B (C4 continuation, Qwen cross-scored) yields $\\Kempirical{=}1$ (1v2 $\\auc = 0.5894$), consistent with Gemma-2-2B at 5K ($\\Kempirical{=}1$, 1v2 $\\auc = 0.5981$). The Gemma family produces $\\Kempirical{=}1$ at both 2B and 27B, suggesting $\\Kempirical$ is model-family-dependent rather than scale-dependent.\n",
      "numLines": 5,
      "startLine": 48,
      "totalLines": 258
    }
  },
  "sourceToolAssistantUUID": "3c5194ab-e430-4500-a2be-2930f07e0c20",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 93 · 2026-05-23T11:14:41.480Z_

```json
{
  "parentUuid": "87b20e5d-0ee6-4d5b-a46b-c365c4694265",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "ee9aa7ce-7ca2-4706-8c1c-03ff8b2f8ef1",
  "timestamp": "2026-05-23T11:14:41.480Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 94 · 2026-05-23T11:14:44.667Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01PDrX6d9sJ14BFJMLNBM4Ui`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
  "old_string": "LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9225$)",
  "new_string": "LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9224$)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ee9aa7ce-7ca2-4706-8c1c-03ff8b2f8ef1",
  "isSidechain": false,
  "requestId": "req_011CbKQNF6toSQ2woAKcKua9",
  "type": "assistant",
  "uuid": "80a7aade-f6cc-4453-b37e-edfae12f35ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BmweP27wWiDFwR1mVitx9F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 536,
      "cache_read_input_tokens": 104800,
      "output_tokens": 228,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 536,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 228,
          "cache_read_input_tokens": 104800,
          "cache_creation_input_tokens": 536,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 536
          },
          "type": "message"
        }
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

_source line 95 · 2026-05-23T11:14:44.676Z_

<details><summary>↩ Tool result · `toolu_01PDrX6d9sJ14BFJMLNBM4Ui`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "80a7aade-f6cc-4453-b37e-edfae12f35ac",
  "isSidechain": false,
  "promptId": "ad64ef57-1e6c-4eb4-b7eb-47fa609a617b",
  "type": "user",
  "uuid": "4b37582f-6fac-4b07-86de-9645ad800dac",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/appendix_extended.tex",
    "oldString": "LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9225$)",
    "newString": "LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9224$)",
    "originalFile": null,
    "structuredPatch": [
      {
        "oldStart": 47,
        "oldLines": 7,
        "newStart": 47,
        "newLines": 7,
        "lines": [
          " \\subsection{Scale and Neural Probe}",
          " \\label{sec:extended_neural_probe}",
          " ",
          "-Cross-scale validation confirms $\\Kempirical = 2$ from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9225$) both exceed $\\theta$, with progressively lower 0v1 signal consistent with larger models generating more human-like text.",
          "+Cross-scale validation confirms $\\Kempirical = 2$ from 1.5B through 8B: Qwen-7B (1v2 $\\auc = 0.6168$ $[0.608, 0.626]$) and LLaMA-3.1-8B (1v2 $\\auc = 0.6123$, 0v1 $= 0.9224$) both exceed $\\theta$, with progressively lower 0v1 signal consistent with larger models generating more human-like text.",
          " Gemma-2-27B (C4 continuation, Qwen cross-scored) yields $\\Kempirical{=}1$ (1v2 $\\auc = 0.5894$), consistent with Gemma-2-2B at 5K ($\\Kempirical{=}1$, 1v2 $\\auc = 0.5981$). The Gemma family produces $\\Kempirical{=}1$ at both 2B and 27B, suggesting $\\Kempirical$ is model-family-dependent rather than scale-dependent.",
          " ",
          " The neural probe yields model-dependent $\\Kempirical^{\\text{neural}}$: $3$ for Qwen (self-familiarity effect from instruction-tuned representations) but $2$ for Pythia; OLMo yields $\\Kempirical^{\\text{neural}} = 1$ (1v2 $\\auc = 0.5054$), consistent with the 15D LightGBM boundary."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "80a7aade-f6cc-4453-b37e-edfae12f35ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 96 · 2026-05-23T11:14:57.788Z_

## 审计总结

**已修复**：
- `experiments_c1.tex` line 49, 54 + `appendix_extended.tex` line 50：LLaMA-8B 0v1 从 `0.9225`（CV估计）改为 `0.9224`（bootstrap估计），与 Table 10 (.9224) 一致。

**需要人工核实 — Mistral-7B**：
论文 Table 10 中 Mistral-7B 的全部 5 个 AUC 值与 registry 中**所有** Mistral 实验都不匹配：

| Pair | 论文 | exp_019 (self) | exp_019b (cross) |
|------|------|----------------|------------------|
| 0v1 | .9170 | .9843 | .9209 |
| 1v2 | .5750 | .5935 | .5695 |
| 2v3 | .5369 | .5402 | .5335 |
| 3v4 | .5174 | .5232 | .5140 |
| 4v5 | .5175 | .5181 | .5184 |

这些值看起来介于 self-scored 和 cross-scored 之间，但不是简单平均。可能来自未注册的实验。请确认数据源。

**Registry 需更新（非论文错误）**：
- `exp_002_olmo_depth` 的 3v4 (0.5034) 和 4v5 (0.4971) 已过时，论文使用的是 `exp_olmo1b_c4_rerun` 的值 (0.5024, 0.4942)。

**可忽略的精度差异**：Gemma-2B 3v4 (Δ=0.0003) 和 4v5 (Δ=0.0001)，在存储精度误差范围内。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4b37582f-6fac-4b07-86de-9645ad800dac",
  "isSidechain": false,
  "requestId": "req_011CbKQNUzZg39j1j8THnHjU",
  "type": "assistant",
  "uuid": "35dd903b-4392-41ea-870a-7031b2a21f70",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WepKzTcVanPE9sYakdS7BZ",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 285,
      "cache_read_input_tokens": 105336,
      "output_tokens": 528,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 285,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 528,
          "cache_read_input_tokens": 105336,
          "cache_creation_input_tokens": 285,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 285
          },
          "type": "message"
        }
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

_source line 97_

```json
{
  "type": "last-prompt",
  "leafUuid": "35dd903b-4392-41ea-870a-7031b2a21f70",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

### Runtime record

_source line 98_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper tables against registry experiments",
  "sessionId": "34d999f9-ba08-4dc3-8d75-ac2750aed5c6"
}
```

---

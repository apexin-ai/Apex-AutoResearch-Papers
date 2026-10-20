# Research conversation: <project_context> # 项目: tax_error_inject_agent ## 运行环境 - 服务器名: autodl-5090 - SSH 账户: root（调用 ssh_execute / submit_traini

**DisPeD: A Controlled Study of Encoder Adaptation for Multi-Turn Jailbreak Detection (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 30
- **Recorded user turns:** 1
- **Tool calls:** 6
- **Original source:** `logs/chats/exported-trajectories/account-3/ae491a69-2268-4f52-bbd5-112d75ec9c55.jsonl`
- **Structured JSON:** [`a5a60608687e29e0b13a.json`](../../sessions/a5/a5a60608687e29e0b13a.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-16T14:53:17.938Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-16T14:53:17.938Z",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "content": "&lt;project_context>\n# 项目: tax_error_inject_agent\n\n## 运行环境\n- 服务器名: autodl-5090\n- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account=\"root\"）\n- SSH 连接命令: ssh autodl-5090  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/autodl-tmp/tax_error_inject_agent\n\n## ⚠️ 活跃约束（必须遵守）\n\n- **C001**: GPU 白名单：仅使用 autodl-5090 cuda:0-3，禁止使用其他服务器或 GPU（原因：本项目分配 4 张 RTX 5090，L1 红线要求明确 GPU 白名单）\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n## 任务：汇总 LLaMA 跨模型验证结果表\n\n### 背景\n项目正在做 taxonomy-guided error injection 研究（negative result paper），核心发现是 Qwen3-8B 上 TaxEI 无优势（TaxEI≈Random），现在用 LLaMA-3.1-8B-Instruct 做跨模型验证。\n\n### 你要做什么\n\n1. **读 registry** 获取所有 `llama31-*` 实验的 metrics\n2. **编制 LLaMA 跨模型结果表**，格式如下：\n\n**LLaMA-3.1-8B Training Metrics:**\n| Seed | Vanilla loss | TaxEI loss | Random loss |\n|------|-------------|------------|-------------|\n| s42  | ... | ... | ... |\n| s0   | ... | ... | ... |\n| s123 | ... | ... | ... |\n\n**LLaMA-3.1-8B Eval (Injected - recovery_rate/success_rate):**\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | ... | ... | ... |\n| s0   | ... | ... | ... |\n| s123 | (pending) | (pending) | (pending) |\n| Mean±SD | ... | ... | ... |\n\n**LLaMA-3.1-8B Clean Eval (success_rate):**\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | ... | ... | ... |\n| s0   | ... | ... | ... |\n| s123 | ... | (pending) | (pending) |\n| Mean±SD | ... | ... | ... |\n\n3. **对比 Qwen3-8B 核心数据**（从 registry 或已知数据）：\n   - Qwen3-8B 5-seed: Vanilla 67.3±4.7%, TaxEI 58.3±6.5%, Random 58.3±8.7%\n   - LLaMA s42: V=74.5%, T=74.5%, R=76.6%（injection penalty 消失）\n   \n4. **写入分析文件**：将结果表和初步分析写入项目的 memory.md（追加到已有内容），包括：\n   - 完整的结果表\n   - LLaMA vs Qwen3-8B 的关键差异总结\n   - 哪些实验还缺（标记为 pending）\n\n### 注意事项\n- 只从 registry 读数据，不要编造数字\n- s123 的 taxei 和 random 还在训练中，标记为 pending\n- 关注 injection penalty：Qwen3-8B 有 ~9pp penalty（67.3→58.3），LLaMA 可能没有\n\n### 产出\n将汇总写入 report.md 的替代：写一个 artifacts 文件到 /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/llama_crossmodel_summary.md，然后用 register_artifact 注册。"
}
```

---

### Runtime record

_source line 2 · 2026-05-16T14:53:17.946Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-16T14:53:17.946Z",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

## Round 1

28 recorded events

### User

_source line 3 · 2026-05-16T14:53:18.002Z_

&lt;project_context>
# 项目: tax_error_inject_agent

## 运行环境
- 服务器名: autodl-5090
- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account="root"）
- SSH 连接命令: ssh autodl-5090  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/autodl-tmp/tax_error_inject_agent

## ⚠️ 活跃约束（必须遵守）

- **C001**: GPU 白名单：仅使用 autodl-5090 cuda:0-3，禁止使用其他服务器或 GPU（原因：本项目分配 4 张 RTX 5090，L1 红线要求明确 GPU 白名单）


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
## 任务：汇总 LLaMA 跨模型验证结果表

### 背景
项目正在做 taxonomy-guided error injection 研究（negative result paper），核心发现是 Qwen3-8B 上 TaxEI 无优势（TaxEI≈Random），现在用 LLaMA-3.1-8B-Instruct 做跨模型验证。

### 你要做什么

1. **读 registry** 获取所有 `llama31-*` 实验的 metrics
2. **编制 LLaMA 跨模型结果表**，格式如下：

**LLaMA-3.1-8B Training Metrics:**
| Seed | Vanilla loss | TaxEI loss | Random loss |
|------|-------------|------------|-------------|
| s42  | ... | ... | ... |
| s0   | ... | ... | ... |
| s123 | ... | ... | ... |

**LLaMA-3.1-8B Eval (Injected - recovery_rate/success_rate):**
| Seed | Vanilla | TaxEI | Random |
|------|---------|-------|--------|
| s42  | ... | ... | ... |
| s0   | ... | ... | ... |
| s123 | (pending) | (pending) | (pending) |
| Mean±SD | ... | ... | ... |

**LLaMA-3.1-8B Clean Eval (success_rate):**
| Seed | Vanilla | TaxEI | Random |
|------|---------|-------|--------|
| s42  | ... | ... | ... |
| s0   | ... | ... | ... |
| s123 | ... | (pending) | (pending) |
| Mean±SD | ... | ... | ... |

3. **对比 Qwen3-8B 核心数据**（从 registry 或已知数据）：
   - Qwen3-8B 5-seed: Vanilla 67.3±4.7%, TaxEI 58.3±6.5%, Random 58.3±8.7%
   - LLaMA s42: V=74.5%, T=74.5%, R=76.6%（injection penalty 消失）
   
4. **写入分析文件**：将结果表和初步分析写入项目的 memory.md（追加到已有内容），包括：
   - 完整的结果表
   - LLaMA vs Qwen3-8B 的关键差异总结
   - 哪些实验还缺（标记为 pending）

### 注意事项
- 只从 registry 读数据，不要编造数字
- s123 的 taxei 和 random 还在训练中，标记为 pending
- 关注 injection penalty：Qwen3-8B 有 ~9pp penalty（67.3→58.3），LLaMA 可能没有

### 产出
将汇总写入 report.md 的替代：写一个 artifacts 文件到 /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/llama_crossmodel_summary.md，然后用 register_artifact 注册。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "a26fdbc5-70f1-431a-b081-2fc1f5ae7466",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-16T14:53:18.001Z_

```json
{
  "parentUuid": "a26fdbc5-70f1-431a-b081-2fc1f5ae7466",
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
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
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
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__update_registry"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "d1068e2f-788f-427f-aa7e-0f18d67952ee",
  "timestamp": "2026-05-16T14:53:18.001Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-16T14:53:18.001Z_

```json
{
  "parentUuid": "d1068e2f-788f-427f-aa7e-0f18d67952ee",
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
  "uuid": "4ab724cb-17d0-4613-ad76-a225ffa5c053",
  "timestamp": "2026-05-16T14:53:18.001Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-16T14:53:18.001Z_

```json
{
  "parentUuid": "4ab724cb-17d0-4613-ad76-a225ffa5c053",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "bf6317f2-fd27-4051-bac7-22114d8de67a",
  "timestamp": "2026-05-16T14:53:18.001Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
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
  "aiTitle": "Compile LLaMA cross-model validation results",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

### Assistant

_source line 8 · 2026-05-16T14:53:25.417Z_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the registry to get all llama31-* experiment metrics.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bf6317f2-fd27-4051-bac7-22114d8de67a",
  "isSidechain": false,
  "requestId": "req_011Cb6SNv4NhxDNjZFf8Nasa",
  "type": "assistant",
  "uuid": "aa18d791-0e51-4b9c-8e01-3da807af81a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WXtZGDBSBUH7XuEqXzizpY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11741,
      "cache_read_input_tokens": 11841,
      "output_tokens": 147,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11741,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 147,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 11741,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11741
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-16T14:53:26.865Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Sr9FF8zmMLTMWtM8wUeRh1`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "aa18d791-0e51-4b9c-8e01-3da807af81a9",
  "isSidechain": false,
  "requestId": "req_011Cb6SNv4NhxDNjZFf8Nasa",
  "type": "assistant",
  "uuid": "d84b12db-b74f-4ce0-be0c-21a4df9693f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WXtZGDBSBUH7XuEqXzizpY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11741,
      "cache_read_input_tokens": 11841,
      "output_tokens": 147,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11741,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 147,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 11741,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11741
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-16T14:53:26.873Z_

<details><summary>↩ Tool result · `toolu_01Sr9FF8zmMLTMWtM8wUeRh1`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d84b12db-b74f-4ce0-be0c-21a4df9693f1",
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "1ac63ef7-7816-464e-bb50-91a6fdc6bbb1",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file",
    "total_deferred_tools": 25
  },
  "sourceToolAssistantUUID": "d84b12db-b74f-4ce0-be0c-21a4df9693f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-16T14:53:29.707Z_

<details><summary>Logged reasoning block</summary>

```text
Let me read the registry to get all llama31-* experiment data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1ac63ef7-7816-464e-bb50-91a6fdc6bbb1",
  "isSidechain": false,
  "requestId": "req_011Cb6SPNQQ3HTXzhW5C2QvA",
  "type": "assistant",
  "uuid": "3bc5ad3e-eaf6-40b5-8660-98fe28ff2701",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U7fQTDg8YtH9TZoqBbvL3S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1358,
      "cache_read_input_tokens": 23582,
      "output_tokens": 268,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1358,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 268,
          "cache_read_input_tokens": 23582,
          "cache_creation_input_tokens": 1358,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1358
          },
          "type": "message"
        }
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

_source line 12 · 2026-05-16T14:53:31.277Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01Bv9Q9w1nTDbXGnFaqrzqTm`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "*"
  ],
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3bc5ad3e-eaf6-40b5-8660-98fe28ff2701",
  "isSidechain": false,
  "requestId": "req_011Cb6SPNQQ3HTXzhW5C2QvA",
  "type": "assistant",
  "uuid": "88555b8a-cd85-4ba3-b82f-7088a4c2553e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U7fQTDg8YtH9TZoqBbvL3S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1358,
      "cache_read_input_tokens": 23582,
      "output_tokens": 268,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1358,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 268,
          "cache_read_input_tokens": 23582,
          "cache_creation_input_tokens": 1358,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1358
          },
          "type": "message"
        }
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

_source line 13 · 2026-05-16T14:53:31.427Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01Hdy4jeVY8PrRs3uUijW5Fd`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "filters": {
    "status": "RUNNING"
  },
  "fields": [
    "*"
  ],
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "88555b8a-cd85-4ba3-b82f-7088a4c2553e",
  "isSidechain": false,
  "requestId": "req_011Cb6SPNQQ3HTXzhW5C2QvA",
  "type": "assistant",
  "uuid": "e7cb726f-c6cb-4161-8118-ba19618dc9f3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U7fQTDg8YtH9TZoqBbvL3S",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1358,
      "cache_read_input_tokens": 23582,
      "output_tokens": 268,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1358,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 268,
          "cache_read_input_tokens": 23582,
          "cache_creation_input_tokens": 1358,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1358
          },
          "type": "message"
        }
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

_source line 14 · 2026-05-16T14:53:32.159Z_

<details><summary>↩ Tool result · `toolu_01Bv9Q9w1nTDbXGnFaqrzqTm`</summary>

```text
Error: result (189,288 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "88555b8a-cd85-4ba3-b82f-7088a4c2553e",
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "8540a05e-7e55-4d46-a57b-90e981fb3b2f",
  "toolUseResult": "Error: result (189,288 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"recovery-random-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:37:24.534Z\", \"updated_at\": \"2026-05-16T14:49:59.675Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --output eval_results/v4_random_recovery_eval_s7.json --device cuda:0 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"eval/alfworld_tasks\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + mini_random_sft_v4_seed7\", \"seed\": 7, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks with error injection\", \"parent\": \"mini_random_sft_v4_seed7\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"log_path\": \"eval_results/v4_random_recovery_eval_s7.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:37:52.029Z\", \"metrics\": {\"recovery_rate\": 0.532, \"detection_rate\": 0, \"total_episodes\": 47}}, \"recovery-random-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:37:23.085Z\", \"updated_at\": \"2026-05-16T14:49:58.929Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --output eval_results/v4_random_recovery_eval_s1.json --device cuda:0 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"eval/alfworld_tasks\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + mini_random_sft_v4_seed1\", \"seed\": 1, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks with error injection\", \"parent\": \"mini_random_sft_v4_seed1\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387\", \"log_path\": \"eval_results/v4_random_recovery_eval_s1.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:37:50.738Z\", \"metrics\": {\"recovery_rate\": 0.511, \"detection_rate\": 0, \"total_episodes\": 47}}, \"llama31-vanilla-s123-clean\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:36:07.599Z\", \"updated_at\": \"2026-05-16T14:36:39.967Z\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python eval/recovery.py --model_path output/llama31-vanilla-s123/v0-20260516-205231/checkpoint-1635 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct/ --task_list eval/eval_tasks_47.json --num_episodes 47 --output eval_results/llama31_vanilla_s123_clean.json --no_inject --seed 123 --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"llama31-vanilla-s123\", \"seed\": 123, \"checkpoint_source\": \"output/llama31-vanilla-s123/v0-20260516-205231/checkpoint-1635\", \"eval_data\": \"valid_unseen\", \"checkpoint_path\": \"output/llama31-vanilla-s123/v0-20260516-205231/checkpoint-1635\", \"log_path\": \"eval_results/llama31_vanilla_s123_clean.log\", \"parent\": \"llama31-vanilla-s123\"}, \"completed_at\": \"2026-05-16T14:36:32.828Z\", \"metrics\": {\"success_rate\": 0.723, \"total_episodes\": 47, \"eval_type\": \"clean\", \"eval_script\": \"eval/recovery.py\", \"output_file\": \"eval_results/llama31_vanilla_s123_clean.json\", \"by_task_type\": {\"look_at_obj_in_light\": 0.833, \"pick_and_place_simple\": 0.625, \"pick_clean_then_place_in_recep\": 0.545, \"pick_cool_then_place_in_recep\": 0.571, \"pick_heat_then_place_in_recep\": 1, \"pick_two_obj_and_place\": 0.857}}}, \"llama31-vanilla-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:52:22.460Z\", \"updated_at\": \"2026-05-16T14:26:04.356Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir output/llama31-vanilla-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"277341\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-vanilla-s123.log\", \"submitted_at\": \"2026-05-16T12:52:22.085Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 123, \"wall_clock_seconds\": 4992.9, \"gpu_hours\": 1.39}, \"hypothesis\": \"Cross-model: LLaMA Vanilla s123 - 3rd seed for 3-seed cross-model validation\", \"checkpoint_path\": \"output/llama31-vanilla-s123/v0-20260516-205231/checkpoint-1635\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:15:35.008Z\", \"metrics\": {\"train_loss\": 0.4, \"final_loss\": 0.254, \"token_acc\": 0.894, \"steps\": 1635, \"epochs\": 3, \"runtime_seconds\": 4234, \"memory_gib\": 29.85}}, \"llama31-taxei-s0-clean\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:05:45.875Z\", \"updated_at\": \"2026-05-16T14:06:24.173Z\", \"hypothesis\": \"Cross-model: LLaMA TaxEI s0 clean eval — baseline task success without injection\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --num_episodes 47 --task_list eval/eval_tasks_47.json --output eval_results/llama31_taxei_s0_clean.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + taxei-s0 LoRA\", \"seed\": 0, \"checkpoint_source\": \"output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\", \"eval_data\": \"clean_eval_47ep\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/llama31_taxei_s0_clean.json\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.766, \"total_episodes\": 47}, \"completed_at\": \"2026-05-16T14:06:24.173Z\"}, \"llama31-taxei-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:52:20.766Z\", \"updated_at\": \"2026-05-16T14:04:47.458Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/injected_eval.py --model_path output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --model_variant taxei --output eval_results/llama31_taxei_s0_eval.json --seed 42 --num_episodes 47\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"278309\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/llama31_taxei_s0_eval.json\", \"submitted_at\": \"2026-05-16T12:52:40.445Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"llama31-taxei-s0\", \"checkpoint_source\": \"output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\", \"eval_data\": \"injected_eval_47ep\", \"model_name\": \"Meta-Llama-3.1-8B-Instruct + taxei-s0 LoRA\", \"seed\": 42, \"data_path\": \"eval/injected_eval.py (built-in ALFWorld tasks)\", \"data_count\": 47, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\", \"wall_clock_seconds\": 4327.0, \"gpu_hours\": 1.2}, \"hypothesis\": \"Cross-model: LLaMA TaxEI s0 injected eval — does taxonomy injection help on LLaMA seed 0?\", \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.745, \"success_rate\": 0.745, \"total_episodes\": 47}, \"completed_at\": \"2026-05-16T14:04:47.458Z\"}, \"llama31-random-s42-clean\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:30:37.651Z\", \"updated_at\": \"2026-05-16T13:19:33.606Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path output/llama31-random-s42/v0-20260516-142300/checkpoint-3387 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --num_episodes 47 --task_list eval/eval_tasks_47.json --output eval_results/llama31_random_s42_clean.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + llama31-random-s42 LoRA\", \"seed\": 42, \"checkpoint_source\": \"output/llama31-random-s42/v0-20260516-142300/checkpoint-3387\", \"eval_data\": \"ALFWorld clean eval 47 tasks\", \"hypothesis\": \"LLaMA Random s42 clean eval - baseline success rate without injection\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.766, \"eval_type\": \"clean\", \"eval_script\": \"eval/recovery.py\", \"total_episodes\": 47, \"output_file\": \"eval_results/llama31_random_s42_clean.json\"}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387\", \"log_path\": \"eval_results/llama31_random_s42_clean.json\", \"completed_at\": \"2026-05-16T11:50:54.372Z\"}, \"llama31-taxei-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:15:57.399Z\", \"updated_at\": \"2026-05-16T12:39:46.148Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 swift sft --model Meta-Llama-3.1-8B-Instruct --dataset sft_taxei_v4.jsonl --output_dir output/llama31-taxei-s0 --lora_rank 16 --num_train_epochs 3 --seed 0\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"262833\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-taxei-s0.log\", \"submitted_at\": \"2026-05-16T09:15:57.070Z\", \"submitted_via\": \"manual_retry_v1\", \"backend\": \"interactive_pts\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 0, \"hypothesis\": \"Cross-model: LLaMA TaxEI s0 - 2nd seed for 3-seed cross-model validation\", \"wall_clock_seconds\": 11561.0, \"gpu_hours\": 3.21}, \"reproduce\": {\"finished_at\": \"2026-05-16T12:28:37.402Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:20:11.090300+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T12:28:42.837165+00:00\"}]}, \"completed_at\": \"2026-05-16T12:28:38.032Z\", \"metrics\": {\"final_train_loss\": 0.32, \"final_token_acc\": 0.88, \"train_steps\": 3387, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\"}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\"}, \"v4-random-recovery-eval-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:44:11.530Z\", \"updated_at\": \"2026-05-16T12:38:01.309Z\", \"spec\": {\"model_name\": \"Qwen3-8B + Random LoRA s123\", \"seed\": 42, \"method\": \"random\", \"eval_type\": \"recovery\", \"parent\": \"v4-random-sft-s123\", \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"eval_data\": \"ALFWorld injected eval (47 episodes)\", \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --output eval_results/v4_random_recovery_eval_s123.json --seed 42 --num_episodes 47\", \"data_path\": \"eval/injected_eval.py\", \"data_count\": 47, \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"log_path\": \"eval_results/v4_random_recovery_eval_s123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T12:07:20.925Z\", \"metrics\": {\"recovery_rate\": 0.66, \"detection_rate\": 0, \"total_episodes\": 47, \"by_operator\": {\"C1_context_truncation\": {\"recovery_rate\": 0.75, \"recovered\": 9, \"total\": 12}, \"P2_sub_goal_deletion\": {\"recovery_rate\": 0.75, \"recovered\": 9, \"total\": 12}, \"P1_step_order_swap\": {\"recovery_rate\": 0.583, \"recovered\": 7, \"total\": 12}, \"C4_observation_masking\": {\"recovery_rate\": 0.545, \"recovered\": 6, \"total\": 11}}}}, \"llama31-vanilla-s0-clean\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:14:53.046Z\", \"updated_at\": \"2026-05-16T12:35:41.228Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --num_episodes 47 --task_list eval/eval_tasks_47.json --output eval_results/llama31_vanilla_s0_clean.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + llama31-vanilla-s0 LoRA\", \"seed\": 0, \"checkpoint_source\": \"output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635\", \"eval_data\": \"ALFWorld clean eval 47 tasks\", \"hypothesis\": \"LLaMA Vanilla s0 clean eval - baseline success rate without injection\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.723, \"eval_type\": \"clean\", \"eval_script\": \"eval/recovery.py\", \"total_episodes\": 47, \"output_file\": \"eval_results/llama31_vanilla_s0_clean.json\"}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635\", \"log_path\": \"eval_results/llama31_vanilla_s0_clean.json\", \"completed_at\": \"2026-05-16T12:35:41.228Z\"}, \"llama31-vanilla-s42-clean\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:14:50.470Z\", \"updated_at\": \"2026-05-16T12:35:18.899Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --num_episodes 47 --task_list eval/eval_tasks_47.json --output eval_results/llama31_vanilla_s42_clean.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + llama31-vanilla-s42 LoRA\", \"seed\": 42, \"checkpoint_source\": \"output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635\", \"eval_data\": \"ALFWorld clean eval 47 tasks\", \"hypothesis\": \"LLaMA Vanilla s42 clean eval - baseline success rate without injection\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.723, \"eval_type\": \"clean\", \"eval_script\": \"eval/recovery.py\", \"total_episodes\": 47, \"output_file\": \"eval_results/llama31_vanilla_s42_clean.json\"}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635\", \"log_path\": \"eval_results/llama31_vanilla_s42_clean.json\", \"completed_at\": \"2026-05-16T12:35:18.899Z\"}, \"recovery-taxei-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:53:18.146Z\", \"updated_at\": \"2026-05-16T12:13:31.737Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/injected_eval.py --model_path checkpoints/mini_taxei_sft_v4_seed7/.../checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --output_file eval_results/v4_taxei_recovery_eval_s7.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/injected_eval.py\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + TaxEI s7 LoRA\", \"seed\": 7, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed7\", \"eval_data\": \"ALFWorld injected eval 47 tasks\", \"hypothesis\": \"Recovery eval TaxEI s7 - complete 5-seed recovery validation\"}, \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.574, \"detection_rate\": 0, \"total_episodes\": 47}, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed7\", \"log_path\": \"eval_results/v4_taxei_recovery_eval_s7.json\", \"completed_at\": \"2026-05-16T12:13:31.737Z\"}, \"llama31-random-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:58:20.799Z\", \"updated_at\": \"2026-05-16T11:59:00.205Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python3 eval/injected_eval.py --model_path output/llama31-random-s0/v0-20260516-171608/checkpoint-3387 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --model_variant random --num_episodes 47 --output eval_results/llama31_random_s0_injected.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + LoRA random s0\", \"seed\": 42, \"checkpoint_source\": \"output/llama31-random-s0/v0-20260516-171608/checkpoint-3387\", \"eval_data\": \"ALFWorld valid_unseen 47 episodes injected\"}, \"checkpoint_path\": \"output/llama31-random-s0/v0-20260516-171608/checkpoint-3387\", \"log_path\": \"eval_results/llama31_random_s0_injected.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T11:58:51.624Z\", \"metrics\": {\"recovery_rate\": 0.745, \"detection_rate\": 0.255, \"success_rate\": 0.745, \"total_episodes\": 47, \"by_operator\": {\"C1_context_truncation\": {\"total\": 12, \"recovered\": 10, \"detected\": 1, \"recovery_rate\": 0.833, \"detection_rate\": 0.083}, \"C4_observation_masking\": {\"total\": 11, \"recovered\": 8, \"detected\": 4, \"recovery_rate\": 0.727, \"detection_rate\": 0.364}, \"P1_step_order_swap\": {\"total\": 12, \"recovered\": 8, \"detected\": 4, \"recovery_rate\": 0.667, \"detection_rate\": 0.333}, \"P2_sub_goal_deletion\": {\"total\": 12, \"recovered\": 9, \"detected\": 3, \"recovery_rate\": 0.75, \"detection_rate\": 0.25}}}}, \"llama31-random-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:16:00.115Z\", \"updated_at\": \"2026-05-16T11:28:10.720Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --output_dir output/llama31-random-s0 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 0 --data_seed 0 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"260936\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-random-s0.log\", \"submitted_at\": \"2026-05-16T09:15:59.761Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9031, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 0, \"wall_clock_seconds\": 7931.0, \"gpu_hours\": 2.2}, \"reproduce\": {\"finished_at\": \"2026-05-16T11:24:56.461Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T11:24:59.790065+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_train_loss\": 0.3368, \"epoch1_loss\": 0.452, \"epoch2_loss\": 0.238, \"epoch3_loss\": 0.134, \"final_token_acc\": 0.9357, \"train_runtime_sec\": 7622, \"train_steps\": 3387, \"peak_memory_gib\": 30.74, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s0/v0-20260516-171608/checkpoint-3387\"}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s0/v0-20260516-171608/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-random-s0.log\", \"completed_at\": \"2026-05-16T11:28:10.720Z\"}, \"llama31-vanilla-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:39:37.086Z\", \"updated_at\": \"2026-05-16T11:21:29.608Z\", \"hypothesis\": \"LLaMA-3.1-8B Vanilla s0 injected eval - cross-model validation seed 0\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/injected_eval.py --model_path output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --model_variant vanilla --seed 0 --num_episodes 47 --output eval_results/llama31_vanilla_s0_injected.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/injected_eval.py\", \"data_count\": 47, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + llama31-vanilla-s0 LoRA\", \"seed\": 0, \"checkpoint_source\": \"output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635\", \"eval_data\": \"ALFWorld injected eval 47 tasks\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T11:05:01.407Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T11:05:03.246Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T11:05:05.820946+00:00\"}]}, \"metrics\": {\"recovery_rate\": 0.745, \"recovery_count\": \"35/47\", \"detection_rate\": 0.277, \"eval_type\": \"injected\", \"eval_script\": \"injected_eval.py\", \"output_file\": \"eval_results/llama31_vanilla_s0_injected.json\", \"C1_context_truncation\": {\"recovery\": 0.667, \"detection\": 0.167}, \"C4_observation_masking\": {\"recovery\": 0.727, \"detection\": 0.364}, \"P1_step_order_swap\": {\"recovery\": 0.917, \"detection\": 0.333}, \"P2_sub_goal_deletion\": {\"recovery\": 0.667, \"detection\": 0.25}}}, \"v4-random-recovery-eval-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:44:10.000Z\", \"updated_at\": \"2026-05-16T10:54:26.532Z\", \"spec\": {\"model_name\": \"Qwen3-8B + LoRA (mini_random_sft_v4_seed0)\", \"seed\": 0, \"method\": \"random\", \"eval_type\": \"recovery\", \"parent\": \"v4-random-sft-s0\", \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\", \"eval_data\": \"ALFWorld 47 episodes with error injection\", \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --output eval_results/v4_random_recovery_eval_s0.json --device cuda:0 --seed 42 --num_episodes 47\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_recovery_eval_s0.json\", \"data_count\": 47}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\", \"log_path\": \"eval_results/v4_random_recovery_eval_s0.json\", \"completed_at\": \"2026-05-16T10:54:19.062Z\", \"metrics\": {\"recovery_rate\": 0.553, \"detection_rate\": 0, \"success_rate\": 0.553, \"total_episodes\": 47, \"by_operator\": {\"C1_context_truncation\": {\"total\": 12, \"recovered\": 7, \"recovery_rate\": 0.583}, \"C4_observation_masking\": {\"total\": 11, \"recovered\": 6, \"recovery_rate\": 0.545}, \"P1_step_order_swap\": {\"total\": 12, \"recovered\": 7, \"recovery_rate\": 0.583}, \"P2_sub_goal_deletion\": {\"total\": 12, \"recovered\": 6, \"recovery_rate\": 0.5}}}}, \"llama31-vanilla-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:15:55.388Z\", \"updated_at\": \"2026-05-16T10:29:59.217Z\", \"spec\": {\"command\": \"swift sft --model Meta-Llama-3.1-8B-Instruct --dataset sft_vanilla_v4.jsonl\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"257144\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-vanilla-s0.log\", \"submitted_at\": \"2026-05-16T09:15:54.991Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 4358, \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 0, \"wall_clock_seconds\": 4158.6, \"gpu_hours\": 1.16, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T10:26:48.334Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:26:50.786934+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635\", \"log_path\": \"/root/runs/tax_error_inject_agent/llama31-vanilla-s0.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T10:29:44.360Z\", \"metrics\": {\"final_train_loss\": 0.398, \"epoch1_loss\": 0.481, \"epoch2_loss\": 0.362, \"epoch3_loss\": 0.273, \"final_token_acc\": 0.909, \"train_runtime_sec\": 4158.6}}, \"eval-rp-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:25:59.082Z\", \"updated_at\": \"2026-05-16T10:26:30.070Z\", \"spec\": {\"hypothesis\": \"TaxEI-RP s7 eval - complete 5-seed recovery-paired injection assessment\", \"model_name\": \"Qwen3-8B + TaxEI-RP LoRA\", \"seed\": 7, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s7/v0-20260516-142303/checkpoint-5415\", \"eval_data\": \"ALFWorld 47 injected tasks\", \"data_path\": \"eval/injected_eval.py (47 ALFWorld tasks)\", \"data_count\": 47, \"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/injected_eval.py --model_path output/v4-taxei-rp-s7/v0-20260516-142303/checkpoint-5415 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --output_file eval_results/v4_taxei_rp_recovery_eval_s7.json\", \"server\": \"autodl-5090\"}, \"metrics\": {\"recovery_rate\": 0.596, \"recovery_count\": \"28/47\", \"detection_rate\": 0}, \"conclusion\": \"success\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_rp_recovery_eval_s7.json\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s7/v0-20260516-142303/checkpoint-5415\", \"completed_at\": \"2026-05-16T10:26:30.070Z\"}, \"v4-taxei-rp-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:22:54.703Z\", \"updated_at\": \"2026-05-16T10:15:30.071Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_rp.jsonl --lora_rank 16 --num_train_epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 7\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/sft_taxei_rp.jsonl\", \"data_count\": 14437, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s7/v0-20260516-142303/checkpoint-5415\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s7/v0-20260516-142303/logging.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T10:11:07.987Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:11:10.984555+00:00\"}]}, \"metrics\": {\"train_loss\": 0.3855, \"token_acc\": 0.9103, \"duration_minutes\": 226.6, \"peak_memory_gib\": 30.25, \"train_samples_per_second\": 3.185}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T10:14:13.073Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s7/v0-20260516-142303/checkpoint-5415\"}, \"recovery-taxei-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:40:11.652Z\", \"updated_at\": \"2026-05-16T09:40:44.285Z\", \"spec\": {\"hypothesis\": \"Recovery eval TaxEI s1 - does TaxEI-trained model recover from injected errors?\", \"model_name\": \"Qwen3-8B + TaxEI LoRA\", \"seed\": 1, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"eval_data\": \"ALFWorld 47 injected tasks\", \"data_path\": \"eval/injected_eval.py (47 ALFWorld tasks)\", \"data_count\": 47, \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --output_file eval_results/v4_taxei_recovery_eval_s1.json\", \"server\": \"autodl-5090\"}, \"metrics\": {\"recovery_rate\": 0.617, \"recovery_count\": \"29/47\", \"detection_rate\": 0, \"C1_context_truncation\": 0.75, \"C4_observation_masking\": 0.636, \"P1_step_order_swap\": 0.583, \"P2_sub_goal_deletion\": 0.5}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_recovery_eval_s1.json\", \"completed_at\": \"2026-05-16T09:40:44.285Z\"}, \"llama31-random-s42-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:14:41.175Z\", \"updated_at\": \"2026-05-16T09:15:28.130Z\", \"spec\": {\"hypothesis\": \"Cross-model: LLaMA Random s42 eval — random injection control on LLaMA\", \"model_name\": \"Meta-Llama-3.1-8B-Instruct + Random LoRA\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387\", \"eval_data\": \"ALFWorld 47 injected tasks\", \"data_path\": \"eval/injected_eval.py (47 ALFWorld tasks)\", \"data_count\": 47, \"command\": \"CUDA_VISIBLE_DEVICES=2 python3 eval/injected_eval.py --model_path output/llama31-random-s42/v0-20260516-142300/checkpoint-3387 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --model_variant random --output_file eval_results/llama31_random_s42.json\", \"server\": \"autodl-5090\"}, \"metrics\": {\"recovery_rate\": 0.766, \"recovery_count\": \"36/47\", \"detection_rate\": 0.298, \"C1_context_truncation\": 0.667, \"C4_observation_masking\": 0.727, \"P1_step_order_swap\": 0.917, \"P2_sub_goal_deletion\": 0.75, \"C1_detection\": 0.417, \"C4_detection\": 0.364, \"P1_detection\": 0.333, \"P2_detection\": 0.083}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/llama31_random_s42.json\", \"completed_at\": \"2026-05-16T09:15:28.130Z\"}, \"llama31-taxei-s42-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:14:40.025Z\", \"updated_at\": \"2026-05-16T09:15:26.908Z\", \"spec\": {\"hypothesis\": \"Cross-model: LLaMA TaxEI s42 eval — does taxonomy-guided injection help on LLaMA?\", \"model_name\": \"Meta-Llama-3.1-8B-Instruct + TaxEI LoRA\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387\", \"eval_data\": \"ALFWorld 47 injected tasks\", \"data_path\": \"eval/injected_eval.py (47 ALFWorld tasks)\", \"data_count\": 47, \"command\": \"CUDA_VISIBLE_DEVICES=1 python3 eval/injected_eval.py --model_path output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387 --base_model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --model_variant taxei --output_file eval_results/llama31_taxei_s42.json\", \"server\": \"autodl-5090\"}, \"metrics\": {\"recovery_rate\": 0.745, \"recovery_count\": \"35/47\", \"detection_rate\": 0.298, \"C1_context_truncation\": 0.833, \"C4_observation_masking\": 0.727, \"P1_step_order_swap\": 0.583, \"P2_sub_goal_deletion\": 0.833, \"C1_detection\": 0.167, \"C4_detection\": 0.364, \"P1_detection\": 0.25, \"P2_detection\": 0.417}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/llama31_taxei_s42.json\", \"completed_at\": \"2026-05-16T09:15:26.908Z\"}, \"recovery-vanilla-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T08:53:10.619Z\", \"updated_at\": \"2026-05-16T08:53:54.916Z\", \"spec\": {\"hypothesis\": \"Recovery eval Vanilla s7 - confirm Recovery≈Resilience\", \"model_name\": \"Qwen3-8B + Vanilla LoRA\", \"seed\": 7, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\", \"eval_data\": \"ALFWorld 47 injected tasks\", \"data_path\": \"eval/injected_eval.py (47 ALFWorld tasks)\", \"data_count\": 47, \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --output_file eval_results/v4_vanilla_recovery_eval_s7.json\", \"server\": \"autodl-5090\"}, \"conclusion\": \"success\", \"metrics\": {\"recovery_rate\": 0.745, \"recovery_count\": \"35/47\", \"detection_rate\": 0, \"C1_context_truncation\": 0.75, \"C4_observation_masking\": 0.727, \"P1_step_order_swap\": 0.75, \"P2_sub_goal_deletion\": 0.75}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_vanilla_recovery_eval_s7.json\", \"completed_at\": \"2026-05-16T08:53:54.916Z\"}, \"recovery-vanilla-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T08:26:23.215Z\", \"updated_at\": \"2026-05-16T08:49:34.621Z\", \"spec\": {\"hypothesis\": \"Recovery eval Vanilla s1 - confirm Recovery≈Resilience\", \"model_name\": \"Qwen3-8B + Vanilla LoRA\", \"seed\": 1, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"eval_data\": \"ALFWorld 47 injected tasks\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T08:32:46.932Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T08:32:48.721Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:32:54.320388+00:00\"}]}, \"metrics\": {\"recovery_rate\": 0.66, \"recovery_count\": \"31/47\", \"detection_rate\": 0, \"C1_context_truncation\": 0.667, \"C4_observation_masking\": 0.545, \"P1_step_order_swap\": 0.667, \"P2_sub_goal_deletion\": 0.75}}, \"llama31-random-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:22:51.516Z\", \"updated_at\": \"2026-05-16T08:46:26.260Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"hypothesis\": \"Cross-model generalizability: LLaMA-3.1-8B Random condition control\", \"command\": \"llamafactory train\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387/\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/logging.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T08:32:16.672Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:32:20.396930+00:00\"}]}, \"metrics\": {\"train_loss\": 0.3366, \"token_acc\": 0.9364, \"train_steps\": 3387, \"train_duration_s\": 7622}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T08:39:26.528Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387\"}, \"llama31-taxei-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:22:49.346Z\", \"updated_at\": \"2026-05-16T08:46:25.092Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"hypothesis\": \"Cross-model generalizability: LLaMA-3.1-8B TaxEI condition to verify Qwen3-8B findings transfer\", \"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset sft_taxei_v4.jsonl --lora_rank 16 --num_train_epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/logging.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T08:36:00.235Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:36:05.288585+00:00\"}]}, \"metrics\": {\"train_loss\": 0.3366, \"token_acc\": 0.9357, \"train_steps\": 3387, \"train_duration_s\": 7782}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T08:39:34.756Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387\"}, \"llama31-vanilla-s42-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T08:07:12.328Z\", \"updated_at\": \"2026-05-16T08:36:24.810Z\", \"spec\": {\"hypothesis\": \"LLaMA-3.1-8B Vanilla s42 injected eval - cross-model baseline\", \"model_name\": \"LLaMA-3.1-8B-Instruct + Vanilla LoRA\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635\", \"eval_data\": \"ALFWorld 47 injected tasks\"}, \"metrics\": {\"recovery_rate\": 0.745, \"recovery_count\": \"35/47\", \"detection_rate\": 0.213, \"C1_context_truncation\": 0.75, \"C4_observation_masking\": 0.727, \"P1_step_order_swap\": 0.75, \"P2_sub_goal_deletion\": 0.75}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-vanilla-s42-eval.log\", \"completed_at\": \"2026-05-16T08:36:24.810Z\"}, \"llama31-vanilla-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:32:19.082Z\", \"updated_at\": \"2026-05-16T07:48:06.140Z\", \"spec\": {\"command\": \"swift sft --model Meta-Llama-3.1-8B-Instruct --dataset sft_vanilla_v4.jsonl --lora_rank 16 --epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"244644\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-vanilla-s42.log\", \"submitted_at\": \"2026-05-16T06:32:18.732Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"hypothesis\": \"Cross-model generalizability: LLaMA-3.1-8B Vanilla baseline\", \"wall_clock_seconds\": 4547.4, \"gpu_hours\": 1.26}, \"reproduce\": {\"finished_at\": \"2026-05-16T07:44:55.468Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T07:44:59.077032+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635\", \"metrics\": {\"train_loss\": 0.40025, \"token_acc\": 0.9067, \"train_steps\": 1635, \"train_duration_s\": 4157}, \"conclusion\": \"success\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-vanilla-s42.log\", \"completed_at\": \"2026-05-16T07:48:06.140Z\"}, \"eval-rp-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:32:34.645Z\", \"updated_at\": \"2026-05-16T06:33:18.281Z\", \"spec\": {\"hypothesis\": \"TaxEI-RP recovery eval seed=42\", \"model_name\": \"Qwen3-8B + TaxEI-RP LoRA\", \"seed\": 42, \"command\": \"python eval/injected_eval.py --model_path v4-taxei-rp-s42 checkpoint --model_variant taxei --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld injected tasks\", \"data_count\": 47, \"gpu\": \"cuda:0\"}, \"metrics\": {\"recovery_rate\": 0.383, \"recovery_count\": \"18/47\", \"C1_context_truncation\": 0.5, \"C4_observation_masking\": 0.273, \"P1_step_order_swap\": 0.5, \"P2_sub_goal_deletion\": 0.25, \"detection_rate\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s42/v0-20260516-101703/checkpoint-5415\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_rp_s42_injected.json\", \"completed_at\": \"2026-05-16T06:33:18.281Z\"}, \"eval-rp-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:27:34.660Z\", \"updated_at\": \"2026-05-16T06:30:59.753Z\", \"failure_reason\": \"\", \"conclusion\": \"success\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:27:37.861045+00:00\"}]}, \"metrics\": {\"recovery_rate\": 0.489, \"detection_rate\": 0, \"episodes\": 47, \"recovered\": 23}, \"spec\": {\"command\": \"python eval_recovery.py --seed 1\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/\", \"data_count\": 47, \"model_name\": \"Qwen3-8B (TaxEI-RP s1)\", \"seed\": 1, \"checkpoint_source\": \"v4-taxei-rp-s1\", \"eval_data\": \"47 ALFWorld clean tasks with error injection\"}, \"log_path\": \"/tmp/eval_rp_s1.log\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_outputs/v4_taxei_rp_s1_injected.json\", \"completed_at\": \"2026-05-16T06:30:48.894Z\"}, \"eval-rp-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:27:52.208Z\", \"updated_at\": \"2026-05-16T06:30:58.894Z\", \"failure_reason\": \"\", \"conclusion\": \"success\", \"reproduce\": {\"finished_at\": \"2026-05-16T06:27:54.715Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:28:01.102430+00:00\"}]}, \"metrics\": {\"recovery_rate\": 0.468, \"detection_rate\": 0, \"episodes\": 47, \"recovered\": 22}, \"spec\": {\"command\": \"python eval_recovery.py --seed 0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/\", \"data_count\": 47, \"model_name\": \"Qwen3-8B (TaxEI-RP s0)\", \"seed\": 0, \"checkpoint_source\": \"v4-taxei-rp-s0\", \"eval_data\": \"47 ALFWorld clean tasks with error injection\"}, \"log_path\": \"/tmp/eval_rp_s0.log\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_outputs/v4_taxei_rp_s0_injected.json\", \"completed_at\": \"2026-05-16T06:30:47.736Z\"}, \"eval-rp-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:27:26.558Z\", \"updated_at\": \"2026-05-16T06:30:58.290Z\", \"failure_reason\": \"\", \"conclusion\": \"success\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:27:29.414786+00:00\"}]}, \"metrics\": {\"recovery_rate\": 0.574, \"detection_rate\": 0, \"episodes\": 47, \"recovered\": 27}, \"spec\": {\"command\": \"python eval_recovery.py --seed 123\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/\", \"data_count\": 47, \"model_name\": \"Qwen3-8B (TaxEI-RP s123)\", \"seed\": 123, \"checkpoint_source\": \"v4-taxei-rp-s123\", \"eval_data\": \"47 ALFWorld clean tasks with error injection\"}, \"log_path\": \"/tmp/eval_rp_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_outputs/v4_taxei_rp_s123_injected.json\", \"completed_at\": \"2026-05-16T06:30:46.571Z\"}, \"v4-taxei-rp-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:16:59.271Z\", \"updated_at\": \"2026-05-16T06:15:41.090Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_rp.jsonl --lora_rank 16 --epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 123\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"223254\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-rp-s123.log\", \"submitted_at\": \"2026-05-16T02:16:58.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/sft_taxei_rp.jsonl\", \"data_count\": 14437, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"hypothesis\": \"Recovery-paired training multi-seed replication (seed=123)\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s123/v0-20260516-101708/checkpoint-5415\", \"wall_clock_seconds\": 13954.9, \"gpu_hours\": 3.88}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:05:08.878Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:05:14.118671+00:00\"}]}, \"metrics\": {\"train_loss\": 0.38524182, \"eval_loss\": null, \"duration_minutes\": 226.5, \"token_acc\": 0.91372913, \"train_samples_per_second\": 3.187, \"peak_memory_gib\": 30.66}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T06:09:33.865Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s123/v0-20260516-101708/checkpoint-5415\"}, \"v4-taxei-rp-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:16:54.022Z\", \"updated_at\": \"2026-05-16T06:15:40.096Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_rp.jsonl --lora_rank 16 --epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"222969\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-rp-s42.log\", \"submitted_at\": \"2026-05-16T02:16:53.716Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/sft_taxei_rp.jsonl\", \"data_count\": 14437, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"hypothesis\": \"If recovery-paired training (TaxEI-RP) also fails to improve over Vanilla, task structure is the primary factor. If it works, recovery pairing is the key missing ingredient from PALADIN.\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s42/v0-20260516-101703/checkpoint-5415\", \"wall_clock_seconds\": 13958.9, \"gpu_hours\": 3.88}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:04:57.317Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:04:59.869491+00:00\"}]}, \"metrics\": {\"train_loss\": 0.38469276, \"eval_loss\": null, \"duration_minutes\": 226.67, \"token_acc\": 0.92487562, \"train_samples_per_second\": 3.185, \"peak_memory_gib\": 30.68}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T06:09:32.658Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s42/v0-20260516-101703/checkpoint-5415\"}, \"v4-taxei-rp-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:18:24.897Z\", \"updated_at\": \"2026-05-16T06:15:38.814Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_rp.jsonl --lora_rank 16 --epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 1\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"224231\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-rp-s1.log\", \"submitted_at\": \"2026-05-16T02:18:24.590Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/sft_taxei_rp.jsonl\", \"data_count\": 14437, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"hypothesis\": \"Recovery-paired training multi-seed replication (seed=1)\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s1/v0-20260516-101834/checkpoint-5415\", \"wall_clock_seconds\": 13870.4, \"gpu_hours\": 3.85}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:05:21.988Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:05:27.447822+00:00\"}]}, \"metrics\": {\"train_loss\": 0.38530399, \"eval_loss\": null, \"duration_minutes\": 226.3, \"token_acc\": 0.91761223, \"train_samples_per_second\": 3.19, \"peak_memory_gib\": 30.17}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T06:09:35.005Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s1/v0-20260516-101834/checkpoint-5415\"}, \"v4-taxei-rp-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:16:56.691Z\", \"updated_at\": \"2026-05-16T06:15:37.765Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_rp.jsonl --lora_rank 16 --epochs 3 --bs 4 --ga 2 --lr 1e-4 --max_length 4096 --seed 0\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"223049\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-rp-s0.log\", \"submitted_at\": \"2026-05-16T02:16:56.390Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/sft_taxei_rp.jsonl\", \"data_count\": 14437, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"hypothesis\": \"Recovery-paired training multi-seed replication (seed=0)\", \"wall_clock_seconds\": 14321.4, \"gpu_hours\": 3.98}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:10:47.000Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:10:49.871145+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3847, \"token_acc\": 0.9065, \"duration_min\": 231.07, \"peak_memory_gib\": 30.37, \"train_samples_per_second\": 3.124}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/output/v4-taxei-rp-s0/v0-20260516-101706/checkpoint-5415\", \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-rp-s0.log\", \"completed_at\": \"2026-05-16T06:15:37.765Z\"}, \"v4-taxei-recovery-eval-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:43.113Z\", \"updated_at\": \"2026-05-16T03:23:08.899Z\", \"spec\": {\"checkpoint_path\": \"eval_results/v4_taxei_recovery_eval_s123.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-recovery-eval-s123.log\"}, \"metrics\": {\"recovery_rate\": 0.617, \"successes\": 29, \"total\": 47, \"detection_rate\": 0}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:23:08.899Z\"}, \"v4-taxei-recovery-eval-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:41.449Z\", \"updated_at\": \"2026-05-16T03:23:07.706Z\", \"spec\": {\"checkpoint_path\": \"eval_results/v4_taxei_recovery_eval_s0.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-recovery-eval-s0.log\"}, \"metrics\": {\"recovery_rate\": 0.468, \"successes\": 22, \"total\": 47, \"detection_rate\": 0}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:23:07.706Z\"}, \"v4-vanilla-recovery-eval-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:39.466Z\", \"updated_at\": \"2026-05-16T03:23:06.630Z\", \"spec\": {\"checkpoint_path\": \"eval_results/v4_vanilla_recovery_eval_s123.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-recovery-eval-s123.log\"}, \"metrics\": {\"recovery_rate\": 0.66, \"successes\": 31, \"total\": 47, \"detection_rate\": 0}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:23:06.630Z\"}, \"v4-vanilla-recovery-eval-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:38.052Z\", \"updated_at\": \"2026-05-16T03:23:05.513Z\", \"spec\": {\"checkpoint_path\": \"eval_results/v4_vanilla_recovery_eval_s0.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-recovery-eval-s0.log\"}, \"metrics\": {\"recovery_rate\": 0.681, \"successes\": 32, \"total\": 47, \"detection_rate\": 0}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:23:05.513Z\"}, \"v4-random-fixed-inject50-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:09:38.067Z\", \"updated_at\": \"2026-05-16T01:31:24.055Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject50_s1/v1-20260516-075754/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject50_s1_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject50 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject50-s1\", \"eval_data\": \"eval_tasks_47.json\", \"hypothesis\": \"v4 Random 50% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\"}, \"metrics\": {\"success_rate\": 0.702, \"successes\": 33, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 8, \"rate\": 0.727}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject50_s1_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-s1-eval.log\", \"completed_at\": \"2026-05-16T01:31:24.055Z\"}, \"v4-taxei-fixed-inject50-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:09:36.875Z\", \"updated_at\": \"2026-05-16T01:31:23.037Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50_s1/v0-20260516-075747/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject50_s1_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject50 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject50-s1\", \"eval_data\": \"eval_tasks_47.json\", \"hypothesis\": \"v4 TaxEI 50% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\"}, \"metrics\": {\"success_rate\": 0.638, \"successes\": 30, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 6, \"rate\": 1}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject50_s1_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50-s1-eval.log\", \"completed_at\": \"2026-05-16T01:31:23.037Z\"}, \"v4-random-fixed-inject50-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:09:39.957Z\", \"updated_at\": \"2026-05-16T01:21:18.406Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject50_s7/v0-20260516-075756/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject50_s7_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject50 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject50-s7\", \"eval_data\": \"eval_tasks_47.json\", \"hypothesis\": \"v4 Random 50% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject50_s7/v0-20260516-075756/checkpoint-1635\", \"log_path\": \"eval_results/v4_random_fixed_inject50_s7_eval.json\"}, \"metrics\": {\"success_rate\": 0.468, \"successes\": 22, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 1, \"rate\": 0.143}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:21:18.406Z\"}, \"v4-taxei-fixed-inject50-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:09:39.016Z\", \"updated_at\": \"2026-05-16T01:21:17.391Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50_s7/v0-20260516-075754/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject50_s7_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject50 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject50-s7\", \"eval_data\": \"eval_tasks_47.json\", \"hypothesis\": \"v4 TaxEI 50% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50_s7/v0-20260516-075754/checkpoint-1635\", \"log_path\": \"eval_results/v4_taxei_fixed_inject50_s7_eval.json\"}, \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:21:17.391Z\"}, \"v4-random-fixed-inject50-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:58:49.123Z\", \"updated_at\": \"2026-05-16T01:06:27.238Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject50.jsonl --output_dir checkpoints/v4_random_fixed_inject50_s7 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --warmup_ratio 0.03 --save_strategy epoch --logging_steps 10 --seed 7 --data_seed 7 --bf16 true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7}, \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — Wave 2.\", \"metrics\": {\"train_loss\": 0.4672, \"token_acc\": 0.9156, \"train_runtime_sec\": 3832, \"memory_gib\": 29.94}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s7/v0-20260516-075756/checkpoint-1635\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s7/v0-20260516-075756/logging.jsonl\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:06:27.238Z\"}, \"v4-taxei-fixed-inject50-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:58:48.153Z\", \"updated_at\": \"2026-05-16T01:06:25.547Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl --output_dir checkpoints/v4_taxei_fixed_inject50_s7 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --warmup_ratio 0.03 --save_strategy epoch --logging_steps 10 --seed 7 --data_seed 7 --bf16 true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — Wave 2.\", \"metrics\": {\"train_loss\": 0.4674, \"token_acc\": 0.9189, \"train_runtime_sec\": 3834, \"memory_gib\": 29.94}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject50_s7/v0-20260516-075754/checkpoint-1635\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject50_s7/v0-20260516-075754/logging.jsonl\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:06:25.547Z\"}, \"v4-random-fixed-inject50-s1-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:59:00.237Z\", \"updated_at\": \"2026-05-16T01:06:21.982Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject50.jsonl --output_dir checkpoints/v4_random_fixed_inject50_s1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --warmup_ratio 0.03 --save_strategy epoch --logging_steps 10 --seed 1 --data_seed 1 --bf16 true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1}, \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion — Wave 2. Retry: bs=4, ga=2.\", \"metrics\": {\"train_loss\": 0.4664, \"token_acc\": 0.9012, \"train_runtime_sec\": 3928, \"memory_gib\": 30.37}, \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s1/v1-20260516-075754/logging.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s1/v1-20260516-075754/checkpoint-1635\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T00:03:39.204Z\"}, \"v4-taxei-fixed-inject50-s1-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:58:59.221Z\", \"updated_at\": \"2026-05-16T01:05:57.456Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl --output_dir checkpoints/v4_taxei_fixed_inject50_s1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --warmup_ratio 0.03 --save_strategy epoch --logging_steps 10 --seed 1 --data_seed 1 --bf16 true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion — Wave 2. Retry: bs=4, ga=2.\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject50_s1/v0-20260516-075747/checkpoint-1635\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject50_s1/v0-20260516-075747/logging.jsonl\", \"completed_at\": \"2026-05-16T01:05:15.340Z\", \"metrics\": {\"train_loss\": 0.4667, \"token_acc\": 0.9072, \"train_runtime_sec\": 3858, \"memory_gib\": 30.37}}, \"v4-random-fixed-inject50-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:58:26.928Z\", \"updated_at\": \"2026-05-15T23:56:49.997Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion — Wave 2.\", \"spec\": {\"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s1/train.log\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T23:55:00.127Z\"}, \"v4-taxei-fixed-inject50-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:54:03.984Z\", \"updated_at\": \"2026-05-15T23:56:49.235Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion — Wave 2.\", \"spec\": {\"log_path\": \"/tmp/v4-taxei-fixed-inject50-s1.log\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T23:55:01.050Z\"}, \"v4-random-fixed-inject25-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:35:00.186Z\", \"updated_at\": \"2026-05-15T23:54:59.193Z\", \"hypothesis\": \"v4 Random 25% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"parent\": \"v4-random-fixed-inject25-s7\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25_s7/v0-20260516-061742/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s7-eval.log\"}, \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T23:54:59.193Z\"}, \"v4-taxei-fixed-inject25-s7-eval-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:49:33.992Z\", \"updated_at\": \"2026-05-15T23:54:58.200Z\", \"hypothesis\": \"v4 TaxEI 25% seed=7 eval (retry, cwd fix) — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"parent\": \"v4-taxei-fixed-inject25-s7\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject25_s7/v0-20260516-053222/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7-eval-r2.log\"}, \"metrics\": {\"success_rate\": 0.574, \"successes\": 27, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 3, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T23:54:58.200Z\"}, \"v4-random-fixed-inject25-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:17:33.574Z\", \"updated_at\": \"2026-05-15T23:19:01.837Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25_s7/v0-20260516-061742/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s7.log\"}, \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection ratio seed=7 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T23:15:25.217Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:15:27.886821+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4254, \"final_step_loss\": 0.265, \"token_acc\": 0.899, \"epochs\": 3, \"steps\": 1635, \"train_runtime_sec\": 3407}, \"completed_at\": \"2026-05-15T23:19:01.837Z\"}, \"v4-recovery-paired-datagen\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:07:23.715Z\", \"updated_at\": \"2026-05-15T23:09:15.501Z\", \"hypothesis\": \"Recovery-paired injection data generation: 711 injected variants × GPT API recovery demos. Each injected trajectory gets a paired recovery continuation from the error state. For recovery-paired SFT training.\", \"metrics\": {\"total_injected_variants\": 760, \"successfully_processed\": 711, \"skipped_no_source_match\": 49, \"operators\": {\"C1_ContextTruncation\": 182, \"C4_ObservationMasking\": 175, \"P1_StepOrderSwap\": 170, \"P2_SubGoalDeletion\": 184}, \"recovery_steps_mean\": 7.6, \"recovery_steps_min\": 1, \"recovery_steps_max\": 46, \"total_recovery_api_calls\": 5408, \"output_file\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/recovery_paired.jsonl\", \"output_lines\": 711, \"output_size_mb\": 20.8, \"log_file\": \"/root/autodl-tmp/tax_error_inject_agent/logs/recovery_paired_gen.log\"}, \"spec\": {\"command\": \"python scripts/generate_recovery_paired.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v2/injected_variants.jsonl\", \"data_count\": 760, \"model_name\": \"gpt-4o\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/recovery_paired/recovery_paired.jsonl\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/logs/recovery_paired_gen.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T23:09:15.501Z\"}, \"v4-taxei-fixed-inject25-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:34:57.410Z\", \"updated_at\": \"2026-05-15T22:55:45.780Z\", \"hypothesis\": \"v4 TaxEI 25% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"parent\": \"v4-taxei-fixed-inject25-s1\", \"spec\": {\"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject25_s1/v0-20260516-052917/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1-eval.log\"}, \"metrics\": {\"success_rate\": 0.638, \"successes\": 30, \"total\": 47, \"eval_split\": \"valid_unseen\", \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 6, \"rate\": 0.857}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T22:55:45.780Z\"}, \"v4-random-fixed-inject25-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:34:59.280Z\", \"updated_at\": \"2026-05-15T22:51:47.662Z\", \"hypothesis\": \"v4 Random 25% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"parent\": \"v4-random-fixed-inject25-s1\", \"spec\": {\"checkpoint_path\": \"checkpoints/v4_random_fixed_inject25_s1/v0-20260516-053219/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s1-eval.log\"}, \"metrics\": {\"success_rate\": 0.723, \"successes\": 34, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 6, \"rate\": 0.857}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T22:51:47.662Z\"}, \"v4-taxei-fixed-inject25-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:34:58.385Z\", \"updated_at\": \"2026-05-15T22:49:15.451Z\", \"hypothesis\": \"v4 TaxEI 25% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"parent\": \"v4-taxei-fixed-inject25-s7\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject25_s7/v0-20260516-053222/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7-eval.log\", \"submitted_at\": \"2026-05-15T22:45:20.960Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject25 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject25-s7\", \"eval_data\": \"eval_tasks_47.json\", \"wall_clock_seconds\": 67.9, \"gpu_hours\": 0.02}, \"reproduce\": {\"finished_at\": \"2026-05-15T22:46:27.057Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T22:46:28.849Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:46:31.066271+00:00\"}]}, \"notes\": \"失败原因: cd /root/tax_error_inject_agent 路径不存在，正确路径为 /root/autodl-tmp/tax_error_inject_agent | 已有成果: 无（启动即失败） | 建议: 修正 cwd 后重试为 v4-taxei-fixed-inject25-s7-eval-r2，等当前 2 个 eval 完成后提交（eval 并行 ≤ 2）\"}, \"v4-taxei-fixed-inject25-s1-eval-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:38:37.902Z\", \"updated_at\": \"2026-05-15T22:45:10.397Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject25_s1/v0-20260516-052917/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"205858\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1-eval-r2.log\", \"submitted_at\": \"2026-05-15T22:38:37.371Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject25 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject25-s1\", \"eval_data\": \"eval_tasks_47.json\", \"wall_clock_seconds\": 393.0, \"gpu_hours\": 0.11}, \"hypothesis\": \"v4 TaxEI 25% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T22:45:10.397Z\"}, \"v4-taxei-fixed-inject25-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:32:12.446Z\", \"updated_at\": \"2026-05-15T22:33:00.087Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject25_s7/v0-20260516-053222/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7.log\"}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio seed=7 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:30:32.348Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:30:36.683523+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4242, \"final_step_loss\": 0.2571, \"token_accuracy\": 0.904, \"train_steps\": 1635, \"train_epochs\": 3, \"train_runtime_sec\": 3430.48, \"train_duration_min\": 57.17, \"train_samples_per_second\": 3.811, \"train_steps_per_second\": 0.477, \"memory_gib\": 17.55, \"data_count\": 4358}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T22:32:54.528Z\"}, \"v4-random-fixed-inject25-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:32:10.005Z\", \"updated_at\": \"2026-05-15T22:32:58.843Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25_s1/v0-20260516-053219/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s1.log\"}, \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:30:26.273Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:30:28.937887+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4261, \"final_step_loss\": 0.2442, \"token_accuracy\": 0.9123, \"train_steps\": 1635, \"train_epochs\": 3, \"train_runtime_sec\": 3417.56, \"train_duration_min\": 56.96, \"train_samples_per_second\": 3.826, \"train_steps_per_second\": 0.478, \"memory_gib\": 18, \"data_count\": 4358}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T22:32:56.713Z\"}, \"v4-taxei-fixed-inject25-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:29:07.506Z\", \"updated_at\": \"2026-05-15T22:29:56.310Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject25_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"199599\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1.log\", \"submitted_at\": \"2026-05-15T21:29:07.235Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject25_s1/v0-20260516-052917/checkpoint-1635\", \"wall_clock_seconds\": 3649.1, \"gpu_hours\": 1.01}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:27:46.845Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:27:49.896536+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4243, \"train_duration_min\": 57.5, \"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T22:29:56.310Z\"}, \"v4-random-fixed-inject10-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:57:41.705Z\", \"updated_at\": \"2026-05-15T22:15:41.386Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"202328\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:57:41.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635\", \"wall_clock_seconds\": 818, \"gpu_hours\": 0.23}, \"hypothesis\": \"v4 Random 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion. 最后一个 10% eval。\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:12:57.609Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:12:59.982752+00:00\"}]}, \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T22:15:41.386Z\"}, \"v4-random-fixed-inject10-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:08.353Z\", \"updated_at\": \"2026-05-15T21:57:11.016Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 7}, \"reproduce\": {\"finished_at\": \"2026-05-15T21:54:51.217Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:54:53.698171+00:00\"}]}, \"metrics\": {\"final_loss\": 0.2352, \"train_loss_avg\": 0.4209, \"final_token_acc\": 0.9066, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3511.93, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.148}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635\", \"conclusion\": \"success\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7.log\", \"completed_at\": \"2026-05-15T21:57:11.016Z\"}, \"v4-random-fixed-inject10-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:05:18.654Z\", \"updated_at\": \"2026-05-15T21:27:48.360Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"198045\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T21:05:18.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\", \"wall_clock_seconds\": 1350.0, \"gpu_hours\": 0.37}, \"hypothesis\": \"v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T21:25:33.786Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:25:36.468478+00:00\"}]}, \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 10, \"success\": 5, \"rate\": 0.5}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 6, \"rate\": 0.857}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:27:48.360Z\"}, \"v4-taxei-fixed-inject10-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:02:22.234Z\", \"updated_at\": \"2026-05-15T21:27:44.185Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"197555\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:02:21.785Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\", \"wall_clock_seconds\": 1522.4, \"gpu_hours\": 0.42}, \"hypothesis\": \"v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T21:19:30.996Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:19:33.518373+00:00\"}]}, \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject10_s7_eval.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:27:44.185Z\"}, \"v4-taxei-fixed-inject10-s1-eval-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:54:05.248Z\", \"updated_at\": \"2026-05-15T21:06:11.418Z\", \"spec\": {\"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s1)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\"}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval (r2, dedicated GPU) — 47 ALFWorld clean tasks.\", \"reproduce\": {\"finished_at\": \"2026-05-15T21:04:33.190Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:04:36.432028+00:00\"}]}, \"metrics\": {\"success_rate\": 0.511, \"successes\": 24, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject10_s1_eval.json\", \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval-r2.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:06:11.418Z\"}, \"v4-taxei-fixed-inject10-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:05.524Z\", \"updated_at\": \"2026-05-15T21:05:01.494Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --seed 7\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"191997\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7.log\", \"submitted_at\": \"2026-05-15T20:01:19.314Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"wall_clock_seconds\": 3683.3, \"gpu_hours\": 1.02}, \"reproduce\": {\"finished_at\": \"2026-05-15T20:59:13.748Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:59:16.071667+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.237, \"train_loss_avg\": 0.4212, \"final_token_acc\": 0.905, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3437, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.102}, \"completed_at\": \"2026-05-15T21:02:42.621Z\"}, \"v4-random-fixed-inject10-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:07.390Z\", \"updated_at\": \"2026-05-15T21:04:23.738Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4_fixed_inject10.jsonl --seed 1\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"192077\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T20:01:21.468Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"wall_clock_seconds\": 3782.3, \"gpu_hours\": 1.05}, \"reproduce\": {\"finished_at\": \"2026-05-15T21:01:51.221Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:01:53.909162+00:00\"}]}, \"metrics\": {\"final_loss\": 0.3096, \"train_loss_avg\": 0.4238, \"final_token_acc\": 0.8902, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3488, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.132}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:04:23.738Z\"}, \"v4-taxei-fixed-inject10-s123-eval-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:40:05.773Z\", \"updated_at\": \"2026-05-15T20:54:14.378Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"194978\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:05.519Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s123)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 848.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"reproduce\": {\"finished_at\": \"2026-05-15T20:50:16.884Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:50:19.215245+00:00\"}]}, \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\", \"completed_at\": \"2026-05-15T20:54:14.378Z\"}, \"v4-random-fixed-inject10-s0-eval-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:40:07.402Z\", \"updated_at\": \"2026-05-15T20:52:32.204Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"195118\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:07.156Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s0)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 745.0, \"gpu_hours\": 0.21}, \"hypothesis\": \"v4 Random 10% seed=0 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"reproduce\": {\"finished_at\": \"2026-05-15T20:50:22.439Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:50:26.585713+00:00\"}]}, \"metrics\": {\"success_rate\": 0.66, \"successes\": 31, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\", \"completed_at\": \"2026-05-15T20:52:32.204Z\"}, \"v4-random-fixed-inject10-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:43.603Z\", \"updated_at\": \"2026-05-15T20:04:12.753Z\", \"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"188022\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:43.056Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_random_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3975.6, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 Random 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A-OOM\", \"completed_at\": \"2026-05-15T20:03:58.662Z\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:41.337Z\", \"updated_at\": \"2026-05-15T20:04:11.865Z\", \"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"187785\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval.log\", \"submitted_at\": \"2026-05-15T18:57:40.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_taxei_fixed_inject10_s123\", \"seed\": 123, \"wall_clock_seconds\": 3977.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A-OOM\", \"completed_at\": \"2026-05-15T20:03:57.889Z\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:45.002Z\", \"updated_at\": \"2026-05-15T20:04:10.985Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject10_s1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"188906\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T18:57:44.756Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"data_path\": \"eval/eval_tasks_47.json\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"wall_clock_seconds\": 3927.9, \"gpu_hours\": 1.09}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T20:03:12.659Z\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-random-fixed-inject10-s123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:59:20.398Z\", \"updated_at\": \"2026-05-15T20:04:09.526Z\", \"hypothesis\": \"v4 Random fixed-size 10% injection seed=123 eval — 47 ALFWorld tasks, dose-response 5-seed expansion\", \"parent\": \"v4-random-fixed-inject10-s123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject10_s123_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s123\", \"eval_data\": \"eval/eval_tasks_47.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123-eval.log\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_s123_eval.json\", \"completed_at\": \"2026-05-15T20:03:32.060Z\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}}, \"v4-taxei-fixed-inject10-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:46.985Z\", \"updated_at\": \"2026-05-15T20:04:06.775Z\", \"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"188410\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:46.725Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s0\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"eval_results/v4_taxei_fixed_inject10_s0_eval.json\", \"model_name\": \"v4_taxei_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3970.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject10_s0_eval.json\", \"completed_at\": \"2026-05-15T20:03:56.888Z\", \"metrics\": {\"success_rate\": 0.702, \"successes\": 33, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 8, \"rate\": 0.727}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}}, \"v4-taxei-fixed-inject10-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:54:17.800Z\", \"updated_at\": \"2026-05-15T18:57:47.705Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject10_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"182703\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T17:54:17.595Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\", \"wall_clock_seconds\": 3728.4, \"gpu_hours\": 1.04}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:53:12.812Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:53:14.974953+00:00\"}]}, \"metrics\": {\"final_loss\": 0.3013, \"train_loss_avg\": 0.4225, \"final_token_acc\": 0.8947, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3469, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.121}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:56:25.993Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\"}, \"v4-random-fixed-inject10-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:54:20.390Z\", \"updated_at\": \"2026-05-15T18:57:42.428Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_random_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"182781\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:54:20.028Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 3802.4, \"gpu_hours\": 1.06}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=123 (4,358 total). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:54:38.478Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:54:40.603963+00:00\"}]}, \"metrics\": {\"final_loss\": 0.3124, \"train_loss_avg\": 0.4236, \"final_token_acc\": 0.8867, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3535.7, \"train_samples_per_second\": 3.698, \"train_steps_per_second\": 0.462, \"memory_gib\": 18.95}, \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:57:42.428Z\"}, \"v4-taxei-fixed-inject10-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:48:24.290Z\", \"updated_at\": \"2026-05-15T18:56:29.231Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_taxei_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"180877\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:48:23.907Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\", \"wall_clock_seconds\": 4085.3, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=123 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 补齐 10% 数据点。\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:47:28.139Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:47:30.511963+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4234, \"final_loss\": 0.3097, \"final_token_acc\": 0.8882, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3497, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:56:29.231Z\"}, \"v4-random-fixed-inject10-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:48:26.373Z\", \"updated_at\": \"2026-05-15T18:56:27.890Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_random_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"180956\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0.log\", \"submitted_at\": \"2026-05-15T17:48:26.104Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\", \"wall_clock_seconds\": 4081.8, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=0 (4,358 total). Dose-response 5-seed expansion — 与 TaxEI 10% 对比 taxonomy 标签效果。\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:47:48.342Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:47:53.242073+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4227, \"final_loss\": 0.276, \"final_token_acc\": 0.9067, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3531, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:56:27.890Z\"}, \"v4-training-dynamics-forward-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:56:31.230Z\", \"updated_at\": \"2026-05-15T17:55:40.616Z\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 bash scripts/run_training_dynamics_v2.sh\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"180322\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\", \"submitted_at\": \"2026-05-15T16:56:31.040Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"training_dynamics\", \"data_count\": 0, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\", \"wall_clock_seconds\": 3546.9, \"gpu_hours\": 0.99}, \"conclusion\": \"success\", \"metrics\": {\"subsets_computed\": [\"vanilla_full\", \"taxei_full\", \"random_full\", \"taxei_inject10\", \"taxei_inject25\", \"taxei_inject50\"], \"taxei_inject50_injected_mean_loss\": 0.8185, \"taxei_inject50_clean_mean_loss\": 0.8514, \"per_operator\": {\"C1_ContextTruncation\": {\"mean\": 0.6489, \"n\": 101}, \"C4_ObservationMasking\": {\"mean\": 0.6782, \"n\": 92}, \"P1_StepOrderSwap\": {\"mean\": 0.6374, \"n\": 89}, \"P2_SubGoalDeletion\": {\"mean\": 0.6542, \"n\": 88}}, \"plots\": [\"subset_comparison\", \"operator_breakdown\", \"dose_response\"], \"output_dir\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\"}, \"completed_at\": \"2026-05-15T17:55:37.917Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\"}, \"v4-taxei-fixed-inject10-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:52:30.170Z\", \"updated_at\": \"2026-05-15T17:55:38.973Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=0 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 10% 是最薄弱环节，仅有 seed=42 一个数据点。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436, \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_taxei_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\", \"log_path\": \"checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/logging.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4238, \"final_loss\": 0.3102, \"final_token_acc\": 0.8822, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3494, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\"}, \"completed_at\": \"2026-05-15T17:55:36.626Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0.log\"}, \"v4-random-seed7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:29:15.592Z\", \"updated_at\": \"2026-05-15T17:43:36.723Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed7_eval.json\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"179098\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7-eval.log\", \"submitted_at\": \"2026-05-15T17:29:24.122Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random SFT seed=7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-seed7\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"wall_clock_seconds\": 852.6, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 Random SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion ← 基于 v4-random-seed7\", \"reproduce\": {\"finished_at\": \"2026-05-15T17:40:45.965Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:40:48.585893+00:00\"}]}, \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T17:43:36.723Z\"}, \"v4-random-seed1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:17:51.435Z\", \"updated_at\": \"2026-05-15T17:32:36.551Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && mkdir -p eval_results && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"178005\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\", \"submitted_at\": \"2026-05-15T17:18:03.664Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 872.9, \"gpu_hours\": 0.24}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:30:35.329Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:30:38.085288+00:00\"}]}, \"metrics\": {\"success_rate\": 0.468, \"successes\": 22, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 2, \"total\": 8, \"rate\": 0.25}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}}}, \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T17:32:36.551Z\"}, \"v4-random-seed7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:10.206Z\", \"updated_at\": \"2026-05-15T17:29:09.688Z\", \"hypothesis\": \"v4 Random SFT seed=7 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --seed 7 --output_dir checkpoints/mini_random_sft_v4_seed7 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:1\", \"pid\": 164126, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:26:13.042Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:26:15.009112+00:00\"}]}, \"metrics\": {\"final_loss\": 0.173, \"final_token_acc\": 0.935, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697192362530058200, \"train_runtime_sec\": 6672, \"memory_gib\": 18.49}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7.log\", \"completed_at\": \"2026-05-15T17:29:09.688Z\"}, \"v4-random-seed1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:21:02.077Z\", \"updated_at\": \"2026-05-15T17:17:33.614Z\", \"spec\": {\"hypothesis\": \"v4 Random SFT seed=1 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 train/sft_train.py --config configs/mini_random_sft_v4_seed1.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_random_v4\", \"data_count\": 1129, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": [\"cuda:0\"], \"pid\": \"163009\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/\", \"submitted_at\": \"2026-05-15T15:23:31Z\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6842.6, \"gpu_hours\": 1.9}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387\", \"metrics\": {\"final_loss\": 0.167, \"final_token_acc\": 0.938, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697000000000000000}, \"completed_at\": \"2026-05-15T17:17:33.614Z\"}, \"v4-taxei-seed1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:39:59.021Z\", \"updated_at\": \"2026-05-15T16:53:41.245Z\", \"hypothesis\": \"v4 TaxEI SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-taxei-seed1\", \"spec\": {\"command\": \"python eval_agent.py --checkpoint checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387 --split valid_unseen\", \"server\": \"autodl-5090\", \"data_path\": \"valid_unseen\", \"data_count\": 47, \"model_name\": \"mini_taxei_sft_v4_seed1/checkpoint-3387\", \"seed\": 1, \"checkpoint_source\": \"v4-taxei-seed1\", \"eval_data\": \"valid_unseen\", \"gpu\": [\"cuda:2\"], \"pid\": 173824, \"log_path\": \"eval_results/v4_taxei_seed1_eval.json\", \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"parent\": \"v4-taxei-seed1\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:53:35.955Z\", \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-vanilla-seed1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:49:28.411Z\", \"updated_at\": \"2026-05-15T16:43:19.834Z\", \"hypothesis\": \"v4 Vanilla SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-vanilla-seed1\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_seed1_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=1)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"gpu\": [\"cuda:0\"]}, \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed1-eval.log\", \"checkpoint_path\": \"eval_results/v4_vanilla_seed1_eval.json\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3}, \"completed_at\": \"2026-05-15T16:42:21.398Z\"}, \"v4-taxei-seed7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:01.513Z\", \"updated_at\": \"2026-05-15T16:40:14.867Z\", \"hypothesis\": \"v4 TaxEI SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-taxei-seed7\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_seed7_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (TaxEI v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed7\", \"gpu\": [\"cuda:3\"], \"pid\": \"165338\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_taxei_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"by_task\": {\"look_at_obj_in_light\": \"4/6 (0.667)\", \"pick_and_place_simple\": \"5/8 (0.625)\", \"pick_clean_then_place_in_recep\": \"5/11 (0.455)\", \"pick_cool_then_place_in_recep\": \"4/7 (0.571)\", \"pick_heat_then_place_in_recep\": \"7/8 (0.875)\", \"pick_two_obj_and_place\": \"4/7 (0.571)\"}}, \"completed_at\": \"2026-05-15T16:40:14.867Z\"}, \"v4-training-dynamics-forward\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:48:36.487Z\", \"updated_at\": \"2026-05-15T16:37:23.642Z\", \"hypothesis\": \"D027 Training Dynamics: Post-hoc forward pass on seed=42 checkpoints (Vanilla/TaxEI/Random + dose-response 10%/25%/50%) — compute per-subset loss (clean vs injected) and per-operator loss (P1/P2/C1/C4). Key finding: training loss SD=0.0004 across seeds but eval SD=8.6pp — memorization-generalization dissociation.\", \"spec\": {\"command\": \"bash scripts/run_training_dynamics.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/\", \"data_count\": 6, \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"metrics\": {\"vanilla_full\": {\"clean_loss\": 0.6853, \"clean_n\": 4358}, \"taxei_full\": {\"clean_loss\": 0.7712, \"injected_loss\": 0.6139, \"clean_n\": 8269, \"injected_n\": 760, \"per_operator\": {\"P1_StepOrderSwap\": 0.6165, \"P2_SubGoalDeletion\": 0.6161, \"C1_ContextTruncation\": 0.5932, \"C4_ObservationMasking\": 0.6298}}, \"random_full\": {\"clean_loss\": 0.7354, \"injected_loss\": 0.5902, \"clean_n\": 8269, \"injected_n\": 760}, \"dose_response\": {\"taxei_10pct\": {\"clean_loss\": 0.6628, \"injected_loss\": 0.6464, \"gap\": -0.0164, \"injected_n\": 70}, \"taxei_25pct\": {\"clean_loss\": 0.701, \"injected_loss\": 0.574, \"gap\": -0.127, \"injected_n\": 168}, \"taxei_50pct\": {\"clean_loss\": 0.8516, \"injected_loss\": 0.6547, \"gap\": -0.1969, \"injected_n\": 370}}, \"key_findings\": \"Clear dose-response: injected-clean gap widens from -0.016 (10%) to -0.127 (25%) to -0.197 (50%). TaxEI operators C1_ContextTruncation consistently lowest loss. Higher injection rates also degrade clean sample loss (0.663→0.701→0.852).\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics/\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics/\", \"completed_at\": \"2026-05-15T16:35:47.805Z\"}, \"v4-taxei-seed1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:40:26.898Z\", \"updated_at\": \"2026-05-15T15:39:39.545Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": \"cuda:2\", \"pid\": 154937}, \"metrics\": {\"final_loss\": 0.1667, \"avg_loss\": 0.3561, \"token_accuracy\": 0.915, \"final_token_acc\": 0.942, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 108.9, \"memory_gib\": 18.49, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:30:06.293Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:30:07.753494+00:00\"}]}, \"conclusion\": \"success\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed1.log\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"completed_at\": \"2026-05-15T15:39:39.545Z\"}, \"v4-taxei-seed7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:40:29.737Z\", \"updated_at\": \"2026-05-15T15:39:16.334Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"metrics\": {\"current_step\": 3387, \"total_steps\": 3387, \"progress_pct\": 100, \"train_loss\": 0.3568, \"final_step_loss\": 0.1753, \"token_acc\": 0.9009, \"final_token_acc\": 0.9328, \"train_runtime_s\": 6591.9, \"epochs\": 3, \"peak_memory_gib\": 18.49, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:32:43.183Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:32:44.276153+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed7.log\", \"completed_at\": \"2026-05-15T15:36:45.958Z\"}, \"v4-vanilla-seed7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:49:11.983Z\", \"updated_at\": \"2026-05-15T15:32:42.490Z\", \"hypothesis\": \"v4 Vanilla SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-vanilla-seed7\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_vanilla_seed7_eval.json --device cuda:1 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"eval/47 ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-vanilla-seed7\", \"gpu\": [\"cuda:1\"], \"pid\": \"160587\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_vanilla_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.745, \"eval_successes\": 35, \"eval_total\": 47, \"vs_seed42_pp\": 12.8}, \"completed_at\": \"2026-05-15T15:32:42.490Z\"}, \"v4-vanilla-seed1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:40:21.621Z\", \"updated_at\": \"2026-05-15T14:49:23.447Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_vanilla_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": \"cuda:0\", \"pid\": 154589, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"log_path\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/\"}, \"metrics\": {\"final_loss\": 0.292, \"avg_loss\": 0.416, \"token_accuracy\": 0.903, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58.8, \"memory_gib\": 17.63, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T14:39:36.578Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T14:39:37.963564+00:00\"}]}, \"conclusion\": \"success\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=1 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"completed_at\": \"2026-05-15T14:49:23.447Z\"}, \"v4-vanilla-seed7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:45:24.536Z\", \"updated_at\": \"2026-05-15T14:46:55.133Z\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=7 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_vanilla_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:1\", \"pid\": 154666}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:20:48.185Z\", \"metrics\": {\"final_loss\": 0.295, \"avg_loss\": 0.415, \"token_accuracy\": 0.898, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 59.4, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed7/v0-20260515-214031/checkpoint-1635\"}}, \"v4-vanilla-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:30:18.314Z\", \"updated_at\": \"2026-05-15T03:29:56.077Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_recovery_eval.json\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=42)\", \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks with error injection\", \"seed\": 42, \"parent\": \"mini-vanilla-sft-v4\", \"checkpoint_path\": \"eval_results/v4_vanilla_recovery_eval.json\", \"log_path\": \"eval_results/v4_vanilla_recovery_eval.json\"}, \"hypothesis\": \"v4 Vanilla SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"recovery_rate\": 0.617, \"detection_rate\": 0, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 9, \"total\": 12, \"rate\": 0.75}, \"C4_observation_masking\": {\"recovered\": 6, \"total\": 11, \"rate\": 0.545}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}}}, \"completed_at\": \"2026-05-14T21:20:15.791Z\"}, \"v4-random-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:43:46.913Z\", \"updated_at\": \"2026-05-15T02:03:49.013Z\", \"hypothesis\": \"v4 Random 50% injection fixed-size eval — 47 tasks clean eval. 与 TaxEI 50% (51.1%) 对比。Random dose-response 最后一点。\", \"spec\": {\"gpu\": [\"cuda:3\"]}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:56:26.837Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:56:28.410747+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.574, \"eval_successes\": 27, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -4.3, \"vs_taxei_50_pp\": 6.3}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject50_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-eval.log\", \"completed_at\": \"2026-05-15T02:00:22.858Z\"}, \"v4-random-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:48:25.777Z\", \"updated_at\": \"2026-05-15T02:03:46.203Z\", \"hypothesis\": \"v4 Random 25% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 25% (48.9%) 对比。\", \"parent\": \"v4-random-fixed-inject25\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"parent\": \"v4-random-fixed-inject25\", \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_path\": \"eval/alfworld_47_clean\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject25)\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"pid\": \"112516\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -6.4, \"vs_taxei_25_pp\": 6.4}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject25_eval.json\", \"completed_at\": \"2026-05-15T01:59:41.894Z\"}, \"v4-random-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:45:08.375Z\", \"updated_at\": \"2026-05-15T02:02:45.338Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection (4,358 total = 2,179 clean + 2,179 injected). 与 TaxEI 50% 对比 taxonomy 标签在高注入比例下是否有差异。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/random_fixed_inject50/v0-20260515-084528/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:39:15.464Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:39:17.014804+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358, \"train_loss\": 0.4338, \"final_step_loss\": 0.2618, \"token_accuracy\": 0.91, \"train_duration_min\": 53.1, \"memory_gib\": 18, \"train_speed_s_per_it\": 1.95}, \"completed_at\": \"2026-05-15T01:43:35.237Z\"}, \"v4-random-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:44.436Z\", \"updated_at\": \"2026-05-15T01:48:07.606Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection (4,358 total). 与 TaxEI 25% (48.9%) 对比 taxonomy 标签在中等注入比例下是否有差异。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject25 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:1\", \"max_steps\": 1635, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:43:59.432Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:44:03.491274+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}, \"completed_at\": \"2026-05-15T01:48:05.171Z\"}, \"v4-random-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:17.994Z\", \"updated_at\": \"2026-05-15T01:42:40.302Z\", \"hypothesis\": \"v4 Random 10% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 10% (61.7%) 对比。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject10_eval.json --device cuda:2\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"110187\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"submitted_at\": \"2026-05-15T01:28:27.422Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10\", \"checkpoint_source\": \"v4-random-fixed-inject10\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_count\": 47, \"data_path\": \"eval/alfworld_47_clean\", \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10)\", \"seed\": 42, \"wall_clock_seconds\": 852.9, \"gpu_hours\": 0.24}, \"parent\": \"v4-random-fixed-inject10\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:42:40.303Z\"}, \"v4-taxei-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:14.823Z\", \"updated_at\": \"2026-05-15T01:38:54.383Z\", \"spec\": {\"command\": \"python eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_taxei_fixed_inject50_eval.json --device cuda:0 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (v4-taxei-fixed-inject50)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"eval_data\": \"ALFWorld valid_unseen 47 tasks clean eval\"}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection eval — 47 tasks clean eval. Dose-response 最后一个数据点。已有：0%=61.7%, 10%=61.7%, 25%=48.9%, 50%=待测。\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -10.6}, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"log_path\": \"/tmp/eval_inject50.log\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T01:37:38.792Z\"}, \"v4-random-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:41.996Z\", \"updated_at\": \"2026-05-15T01:31:01.715Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection (4,358 total). 与 TaxEI 10% (61.7%) 对比 taxonomy 标签在低注入比例下是否有差异。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=2 && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject10 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"104655\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T00:28:19.537Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"wall_clock_seconds\": 3546.1, \"gpu_hours\": 0.99}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:26:29.568Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:26:31.003606+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4226, \"final_step_loss\": 0.3079, \"token_accuracy\": 0.9, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 57}, \"completed_at\": \"2026-05-15T01:27:25.646Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\"}, \"v4-taxei-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:38.284Z\", \"updated_at\": \"2026-05-15T01:25:47.611Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio (4,358 total = 2,179 clean + 2,179 injected). Dose-response 最后一个点，完成后有完整曲线 0%→10%→25%→50%。\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --learning_rate 1e-4\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"104236\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50.log\", \"submitted_at\": \"2026-05-15T00:27:51.219Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"wall_clock_seconds\": 3476.4, \"gpu_hours\": 0.97}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:22:23.688Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:22:25.093365+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.259, \"token_accuracy\": 0.911, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 53.1}, \"completed_at\": \"2026-05-15T01:25:47.611Z\"}, \"v4-random-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:14:30.699Z\", \"updated_at\": \"2026-05-15T00:27:24.291Z\", \"hypothesis\": \"v4 Random SFT seed=123 eval — 47 tasks clean eval. Multi-seed: seed=42 66.0%, seed=0 55.3%, seed=123 待测。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=1 && cd /root/autodl-tmp/tax_error_inject_agent && python eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 102888, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"submitted_at\": \"2026-05-15T00:14:42.930Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"eval_data\": \"47 tasks clean eval (no injection)\", \"parent\": \"v4-random-seed123\", \"tmux_session\": \"v4-random-seed123-eval\", \"log_file\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"wall_clock_seconds\": 740.0, \"gpu_hours\": 0.21}, \"conclusion\": \"negative\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"completed_at\": \"2026-05-15T00:27:02.930Z\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-taxei-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:53.016Z\", \"updated_at\": \"2026-05-15T00:14:40.327Z\", \"hypothesis\": \"v4 TaxEI 25% injection fixed-size eval — 48.9% (23/47), 显著低于 vanilla baseline 65.3%（-16.4pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"checkpoint_source\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject25-r2\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject25)\", \"seed\": 42}, \"metrics\": {\"eval_success_rate\": 0.489, \"eval_successes\": 23, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 4, \"total\": 6, \"rate\": 0.667}, \"pick_and_place_simple\": {\"success\": 3, \"total\": 8, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject25_eval.json\", \"log_path\": \"/tmp/v4_taxei_fixed_inject25_eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:30.429Z\"}, \"v4-taxei-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:52.584Z\", \"updated_at\": \"2026-05-15T00:14:38.874Z\", \"hypothesis\": \"v4 TaxEI 10% injection fixed-size eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject10_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"tmux_session\": \"eval_inject10\", \"checkpoint_source\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject10\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10)\", \"seed\": 42, \"log_path\": \"/tmp/v4_taxei_fixed_inject10_eval.log\"}, \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject10_eval.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.992Z\"}, \"v4-taxei-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:07.489Z\", \"updated_at\": \"2026-05-15T00:14:37.513Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed123_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 100600, \"model_name\": \"Qwen3-8B + LoRA (taxei v4 seed=123)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed123\", \"checkpoint_path\": \"eval_results/v4_taxei_seed123_eval.json\", \"log_path\": \"/tmp/v4_taxei_seed123_eval.log\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47}, \"hypothesis\": \"v4 TaxEI SFT seed=123 eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。multi-seed verification, 9029 samples。\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.055Z\"}, \"v4-random-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.441Z\", \"updated_at\": \"2026-05-14T23:52:15.056Z\", \"hypothesis\": \"v4 Random SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 93477, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123.log\", \"submitted_at\": \"2026-05-14T21:59:16.545Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6778.5, \"gpu_hours\": 1.88}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:50:09.168Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:50:10.389568+00:00\"}]}, \"metrics\": {\"train_loss\": 0.35484016, \"final_loss\": 0.16766574, \"token_accuracy\": 0.94187103, \"avg_token_accuracy\": 0.90849673, \"train_steps\": 3387, \"train_epochs\": 3, \"train_runtime_sec\": 6609.3556, \"train_duration_min\": 110.2, \"train_samples_per_second\": 4.098, \"train_steps_per_second\": 0.512, \"train_speed_s_per_it\": 1.951, \"memory_gib\": 18.49}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:52:15.056Z\"}, \"v4-taxei-fixed-inject25-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:32:41.837Z\", \"updated_at\": \"2026-05-14T23:50:46.230Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio retry (4,358 total = 3,268 clean + 1,090 injected). 修复 CUDA_VISIBLE_DEVICES，显式设 =3。\", \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=3 && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --output_dir checkpoints/taxei_fixed_inject25 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 96835, \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"note\": \"manual tmux with explicit CUDA_VISIBLE_DEVICES=3, fixing r1 OOM\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.285, \"token_accuracy\": 0.893, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:46.230Z\"}, \"v4-taxei-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:52.707Z\", \"updated_at\": \"2026-05-14T23:50:45.829Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio (4,358 total = 3,922 clean + 436 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --output_dir output/v4-fixed-inject10 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"94635\", \"log_path\": \"/tmp/v4-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T06:12:34Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.308, \"token_accuracy\": 0.888, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:45.829Z\"}, \"v4-taxei-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:53.209Z\", \"updated_at\": \"2026-05-14T23:45:26.890Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio (4,358 total = 3,268 clean + 1,090 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject25.jsonl --output_dir output/v4-fixed-inject25 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"96835\", \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"submitted_at\": \"2026-05-15T06:31:44Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"note\": \"r1 (PID 95170) OOM on cuda:0 — submit_training_job failed to pass CUDA_VISIBLE_DEVICES. Resubmitted manually via tmux with explicit export CUDA_VISIBLE_DEVICES=3.\"}, \"conclusion\": \"failed\", \"failure_reason\": \"CUDA_VISIBLE_DEVICES 未生效，模型加载到 cuda:0 导致 OOM（与 seed123 训练冲突）\", \"completed_at\": \"2026-05-14T23:45:26.890Z\"}, \"v4-taxei-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.191Z\", \"updated_at\": \"2026-05-14T23:43:38.819Z\", \"hypothesis\": \"v4 TaxEI SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 92263, \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed123.log\", \"submitted_at\": \"2026-05-14T21:50:17.845Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6801.0, \"gpu_hours\": 1.89}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:41:32.774Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:41:33.984355+00:00\"}]}, \"metrics\": {\"final_loss\": 0.35506879, \"token_accuracy\": 0.89978214, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 109.2, \"train_runtime_sec\": 6549.432, \"train_speed_s_per_it\": 1.934, \"memory_gib\": 18.49}, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:43:38.819Z\"}, \"v4-random-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:04:57.591Z\", \"updated_at\": \"2026-05-14T22:00:43.285Z\", \"hypothesis\": \"v4 Random SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla/taxei recovery eval.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_recovery_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 90124, \"model_name\": \"Qwen3-8B + LoRA (random SFT v4)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387\", \"eval_data\": \"valid_unseen (47 episodes)\", \"log_path\": \"/tmp/v4_random_recovery_eval.log\", \"output_path\": \"eval_results/v4_random_recovery_eval.json\", \"data_path\": \"valid_unseen\", \"data_count\": 47}, \"conclusion\": \"success\", \"checkpoint_path\": \"eval_results/v4_random_recovery_eval.json\", \"completed_at\": \"2026-05-14T21:42:07.544Z\", \"metrics\": {\"recovery_rate\": 0.638, \"detection_rate\": 0, \"successes\": 30, \"total\": 47, \"source\": \"json-file-verified\", \"note\": \"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\"}}, \"v4-taxei-recovery-eval-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:23:55.110Z\", \"updated_at\": \"2026-05-14T21:46:19.993Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python3 eval/injected_eval.py --model_path checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_recovery_eval_r2.json\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (mini_taxei_sft_v4 checkpoint-3387)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\", \"eval_data\": \"47 episodes with error injection (4 operators: C1_context_truncation, C4_observation_masking, P1_step_order_swap, P2_sub_goal_deletion)\", \"data_path\": \"eval/injected_eval.py\", \"data_count\": 47, \"hypothesis\": \"v4 TaxEI SFT seed=42 recovery eval retry — 47 episodes with error injection, measuring detection/recovery/success rates. Previous attempt reported process dead 5x.\", \"pid\": 90519, \"log_path\": \"/tmp/v4_taxei_recovery_eval_r2.log\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"eval_results/v4_taxei_recovery_eval_r2.json\", \"completed_at\": \"2026-05-14T21:42:08.000Z\", \"metrics\": {\"recovery_rate\": 0.596, \"detection_rate\": 0, \"total_episodes\": 47, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 8, \"total\": 12, \"rate\": 0.667}, \"C4_observation_masking\": {\"recovered\": 7, \"total\": 11, \"rate\": 0.636}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 6, \"total\": 12, \"rate\": 0.5}}}}, \"v4-taxei-seed0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.278Z\", \"updated_at\": \"2026-05-14T21:21:53.154Z\", \"hypothesis\": \"v4 TaxEI SFT seed=0 eval — multi-seed verification, 9029 samples, testing TaxEI injection stability\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed0_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei v4 seed=0)\", \"seed\": 0, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed0\", \"checkpoint_path\": \"eval_results/v4_taxei_seed0_eval.json\", \"log_path\": \"eval_results/v4_taxei_seed0_eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47, \"vs_seed42_pp\": -14.9}, \"completed_at\": \"2026-05-14T21:20:13.351Z\"}, \"v4-random-seed0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.456Z\", \"updated_at\": \"2026-05-14T21:21:52.271Z\", \"hypothesis\": \"v4 Random SFT seed=0 eval — multi-seed verification, 9029 samples, testing random injection stability\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed0_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random v4 seed=0)\", \"seed\": 0, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-random-seed0\", \"log_path\": \"eval_results/v4_random_seed0_eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_seed42_pp\": -10.7}, \"checkpoint_path\": \"eval_results/v4_random_seed0_eval.json\", \"completed_at\": \"2026-05-14T21:20:14.339Z\"}, \"v4-taxei-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:40:41.154Z\", \"updated_at\": \"2026-05-14T21:20:17.664Z\", \"spec\": {\"hypothesis\": \"D010 Phase 2: Recovery eval with action injection on TaxEI seed=42 checkpoint — measuring TaxEI-trained model's recovery ability vs vanilla\", \"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/injected_eval.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --device cuda:0 --seed 42 --output eval_results/v4_taxei_recovery_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 87614, \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + TaxEI LoRA v4 checkpoint-3387\", \"seed\": 42, \"checkpoint_source\": \"mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\", \"eval_data\": \"ALFWorld valid_unseen 47 tasks with action injection\", \"checkpoint_path\": \"eval_results/v4_taxei_recovery_eval.json\", \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-recovery-eval.log\"}, \"hypothesis\": \"v4 TaxEI SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla recovery eval.\", \"reproduce\": {\"finished_at\": \"2026-05-14T20:58:38.335Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T20:58:38.665Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:58:39.601019+00:00\"}]}, \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"recovery_rate\": 0.596, \"detection_rate\": 0}}, \"v4-vanilla-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.635Z\", \"updated_at\": \"2026-05-14T20:43:48.780Z\", \"hypothesis\": \"v4 Vanilla SFT seed=123 eval — multi-seed verification, 4358 samples, comparing with seed=42 baseline (61.7%)\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_vanilla_seed123_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=123)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635\", \"log_path\": \"/tmp/v4_vanilla_seed123_eval.log\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-vanilla-seed123\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T20:37:11.382Z\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3, \"vs_seed0_pp\": -2.1, \"per_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}}, \"v4-random-seed0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:03.440Z\", \"updated_at\": \"2026-05-14T19:36:31.263Z\", \"hypothesis\": \"v4 Random SFT seed=0 (multi-seed verification) — 9,029 samples, same hyperparams as seed=42, testing result stability\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"server\": \"autodl-5090\", \"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 0\", \"gpu\": \"cuda:2\", \"pid\": 72303, \"log_path\": \"/root/runs/tax_error_inject_agent/v4-random-seed0.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\"}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.912, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}, \"completed_at\": \"2026-05-14T19:35:39.420Z\"}, \"v4-taxei-seed0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:02.696Z\", \"updated_at\": \"2026-05-14T19:36:29.716Z\", \"hypothesis\": \"v4 TaxEI SFT seed=0 (multi-seed verification) — 9,029 samples, same hyperparams as seed=42, testing result stability\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"server\": \"autodl-5090\", \"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 0\", \"gpu\": \"cuda:1\", \"pid\": 71822, \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-seed0.log\", \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387\"}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.917, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}, \"completed_at\": \"2026-05-14T19:35:37.503Z\"}, \"v4-vanilla-seed0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.093Z\", \"updated_at\": \"2026-05-14T19:30:45.170Z\", \"hypothesis\": \"v4 Vanilla SFT seed=0 eval — multi-seed verification, 4358 samples, comparing with seed=42 baseline (61.7%)\", \"spec\": {\"checkpoint_path\": \"eval_results/v4_vanilla_seed0_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed0-eval.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T19:01:19.696Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:01:20.697938+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"vs_seed42_pp\": 6.4, \"mcnemar_vs_seed42_p\": 0.375, \"discordant_pairs\": 5, \"per_task\": {\"look_at_obj_in_light\": \"5/6 (83.3%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"4/7 (57.1%)\", \"pick_heat_then_place\": \"7/8 (87.5%)\", \"pick_two_obj_and_place\": \"5/7 (71.4%)\"}}, \"completed_at\": \"2026-05-14T19:29:37.198Z\"}, \"v4-vanilla-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:45:23.836Z\", \"updated_at\": \"2026-05-14T19:29:24.021Z\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=123 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir checkpoints/mini_vanilla_sft_v4_seed123 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 123 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 77937, \"log_path\": \"checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/logging.jsonl\", \"submitted_at\": \"2026-05-14T18:20:42.388Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed123\", \"note\": \"OOM on first attempt (v0), restarted as v1 with PID 77937\", \"wall_clock_seconds\": 3941.6, \"gpu_hours\": 1.09}, \"reproduce\": {\"finished_at\": \"2026-05-14T19:26:23.312Z\"}, \"failure_reason\": \"v0 OOM at model loading (GPU 3 occupied by another process, 18.21 GiB in use). v1 (PID 77937) actually completed 1635/1635 steps. Cron caught v0's EXIT_CODE=1. Verifying checkpoint validity...\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:26:23.949Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:26:24.909318+00:00\"}]}, \"metrics\": {\"final_loss\": 0.288, \"token_accuracy\": 0.903, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58.9}}, \"v4-vanilla-seed0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:01.929Z\", \"updated_at\": \"2026-05-14T18:46:58.919Z\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=0 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"server\": \"autodl-5090\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=0 swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir checkpoints/mini_vanilla_sft_v4_seed0 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 0 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"gpu\": \"cuda:0\", \"pid\": 71959, \"log_path\": \"checkpoints/mini_vanilla_sft_v4_seed0/v0-20260515-014317/logging.jsonl\", \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed0/v0-20260515-014317/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T18:42:56.365Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:42:57.338365+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.297, \"avg_loss\": 0.416, \"token_accuracy\": 0.902, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T18:45:18.121Z\"}, \"traj_collect_500\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:45:21.504Z\", \"updated_at\": \"2026-05-14T16:28:02.238Z\", \"spec\": {\"command\": \"python collect_trajectories.py --target 500\", \"server\": \"autodl-5090\", \"data_path\": \"data/trajectories/\", \"data_count\": 575, \"model_name\": \"trajectory_collector\", \"seed\": 0, \"pid\": 11045, \"gpu\": \"none (CPU task)\", \"hypothesis\": \"GPT-5.2 可作为 teacher 在 ALFWorld 中收集高质量成功轨迹（预期成功率≥93%）\"}, \"metrics\": {\"successful_trajectories\": 501, \"failed_trajectories\": 213, \"total_attempts\": 714, \"success_rate\": 0.702, \"api_cost_usd\": 8.86, \"collection_time_sec\": 5245}, \"conclusion\": \"negative\", \"checkpoint_path\": \"data/trajectories/successful_trajectories.jsonl\", \"log_path\": \"/tmp/collect_500.log\", \"completed_at\": \"2026-05-14T12:21:11.941Z\"}, \"mini-vanilla-sft\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:51:41.382Z\", \"updated_at\": \"2026-05-14T10:54:48.860Z\", \"hypothesis\": \"Vanilla trajectory SFT baseline for comparison with TaxEI\", \"spec\": {\"command\": \"python3 scripts/train_sft.py --data data/sft_data/vanilla_train.jsonl --output checkpoints/mini_vanilla_sft/ --model Qwen3-8B --lora_rank 16 --seed 42 --epochs 3 --lr 1e-4\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"41874\", \"log_path\": \"eval_results/mini_vanilla_clean.json\", \"submitted_at\": \"2026-05-14T10:54:31.029Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/sft_data/vanilla_train.jsonl\", \"data_count\": 278, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"hypothesis\": \"Vanilla SFT on clean trajectories as baseline for comparison\", \"checkpoint_path\": \"checkpoints/mini_vanilla_sft/v0-20260514-181708/checkpoint-54\", \"wall_clock_seconds\": 17.8, \"gpu_hours\": 0.0}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T10:54:20.210Z\", \"metrics\": {\"eval_success_rate\": 0.149, \"eval_successes\": 7, \"eval_total\": 47, \"vs_baseline_pp\": -27.7, \"per_task\": {\"look_at_obj_in_light\": \"0/6 (0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"2/11 (18.2%)\", \"pick_cool_then_place\": \"0/7 (0%)\", \"pick_heat_then_place\": \"3/8 (37.5%)\", \"pick_two_obj_and_place\": \"0/7 (0%)\"}, \"train_steps\": 54, \"train_duration_min\": 5}}, \"mini-taxei-sft\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:51:40.784Z\", \"updated_at\": \"2026-05-14T10:54:46.174Z\", \"hypothesis\": \"TaxEI injection + recovery SFT improves over vanilla SFT on ALFWorld 47-task eval\", \"spec\": {\"command\": \"python3 scripts/train_sft.py --data data/sft_data/taxei_train.jsonl --output checkpoints/mini_taxei_sft/ --model Qwen3-8B --lora_rank 16 --seed 42 --epochs 3 --lr 1e-4\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"41263\", \"log_path\": \"eval_results/mini_taxei_clean.json\", \"submitted_at\": \"2026-05-14T10:53:16.579Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/sft_data/taxei_train.jsonl\", \"data_count\": 278, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/mini_taxei_sft/v0-20260514-181630/checkpoint-195\", \"hypothesis\": \"TaxEI error injection + recovery SFT improves over vanilla SFT and baseline\", \"wall_clock_seconds\": 63.1, \"gpu_hours\": 0.04}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T10:54:19.721Z\", \"metrics\": {\"eval_success_rate\": 0.447, \"eval_successes\": 21, \"eval_total\": 47, \"vs_baseline_pp\": 2.1, \"per_task\": {\"look_at_obj_in_light\": \"3/6 (50.0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"1/7 (14.3%)\", \"pick_heat_then_place\": \"6/8 (75.0%)\", \"pick_two_obj_and_place\": \"3/7 (42.9%)\"}, \"train_steps\": 195, \"train_duration_min\": 16.3}}, \"vanilla-react-baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:20:00.119Z\", \"updated_at\": \"2026-05-14T10:54:35.171Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/models/Qwen/Qwen3-8B --eval_split valid_unseen --no_inject (MAX_STEPS=50 hardcoded)\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld valid_unseen (47/85 tasks, solvable=True filter, pick_and_place_with_movable_recep excluded 0/11)\", \"data_count\": 47, \"model_name\": \"Qwen3-8B (zero-shot, enable_thinking=False)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"hypothesis\": \"Qwen3-8B zero-shot ReAct 在 ALFWorld valid_unseen 的基线成功率，作为 SFT 对比的 lower bound\", \"checkpoint_path\": \"N/A (zero-shot, no training)\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/vanilla_react_baseline.json\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.426, \"total_tasks\": 47, \"successes\": 20, \"per_task_type\": {\"pick_heat_then_place\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"look_at_obj_in_light\": {\"success\": 3, \"total\": 6, \"rate\": 0.5}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_cool_then_place\": {\"success\": 0, \"total\": 7, \"rate\": 0}}}, \"completed_at\": \"2026-05-14T08:58:00.892Z\"}, \"sft-dryrun-73\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:19:34.694Z\", \"updated_at\": \"2026-05-14T08:20:00.752Z\", \"spec\": {\"command\": \"swift sft --config configs/sft_vanilla.yaml (dry-run, 1 epoch, bs=1, max_length=2048)\", \"server\": \"autodl-5090\", \"data_path\": \"data/trajectories/ (124 successful trajectories)\", \"data_count\": 124, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:0\", \"hypothesis\": \"SFT pipeline 端到端验证：注入→格式化→训练流程是否正常工作\", \"checkpoint_path\": \"checkpoints/dryrun_sft_v2/v0-20260514-161410/checkpoint-8/\", \"log_path\": \"checkpoints/dryrun_sft_v2/v0-20260514-161410/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T08:19:52.165Z\", \"metrics\": {\"train_loss_init\": 2.436, \"train_loss_final\": 1.543, \"train_loss_avg\": 1.894, \"peak_memory_gib\": 19.22, \"steps\": 8, \"duration_sec\": 42, \"data_vanilla\": 124, \"data_injected_dryrun\": 96, \"injected_failed\": 4}}}, \"count\": 128, \"total\": 128, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5366}}"
    }
  },
  "sourceToolAssistantUUID": "88555b8a-cd85-4ba3-b82f-7088a4c2553e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 15_

```json
{
  "type": "last-prompt",
  "leafUuid": "8540a05e-7e55-4d46-a57b-90e981fb3b2f",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

### Runtime record

_source line 16_

```json
{
  "type": "ai-title",
  "aiTitle": "Compile LLaMA cross-model validation results",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

### Tool result

_source line 17 · 2026-05-16T14:53:32.600Z_

<details><summary>↩ Tool result · `toolu_01Hdy4jeVY8PrRs3uUijW5Fd`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"llama31-random-s123\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:52:25.749Z\", \"updated_at\": \"2026-05-16T12:53:57.052Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --output_dir output/llama31-random-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"277565\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-random-s123.log\", \"submitted_at\": \"2026-05-16T12:52:25.330Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 123}, \"hypothesis\": \"Cross-model: LLaMA Random s123 - 3rd seed for 3-seed cross-model validation\"}, \"llama31-taxei-s123\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:52:24.059Z\", \"updated_at\": \"2026-05-16T12:53:54.498Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_taxei_v4.jsonl --output_dir output/llama31-taxei-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"277419\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-taxei-s123.log\", \"submitted_at\": \"2026-05-16T12:52:23.670Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 123}, \"hypothesis\": \"Cross-model: LLaMA TaxEI s123 - 3rd seed for 3-seed cross-model validation\"}}, \"count\": 2, \"total\": 2, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4226}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e7cb726f-c6cb-4161-8118-ba19618dc9f3",
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "57d54223-a1cd-4bde-af6c-c1d8a84c67ab",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"llama31-random-s123\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-16T12:52:25.749Z\\\", \\\"updated_at\\\": \\\"2026-05-16T12:53:57.052Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --output_dir output/llama31-random-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"277565\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/llama31-random-s123.log\\\", \\\"submitted_at\\\": \\\"2026-05-16T12:52:25.330Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/sft_random_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B-Instruct\\\", \\\"seed\\\": 123}, \\\"hypothesis\\\": \\\"Cross-model: LLaMA Random s123 - 3rd seed for 3-seed cross-model validation\\\"}, \\\"llama31-taxei-s123\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-16T12:52:24.059Z\\\", \\\"updated_at\\\": \\\"2026-05-16T12:53:54.498Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_taxei_v4.jsonl --output_dir output/llama31-taxei-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"277419\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/llama31-taxei-s123.log\\\", \\\"submitted_at\\\": \\\"2026-05-16T12:52:23.670Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/sft_taxei_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B-Instruct\\\", \\\"seed\\\": 123}, \\\"hypothesis\\\": \\\"Cross-model: LLaMA TaxEI s123 - 3rd seed for 3-seed cross-model validation\\\"}}, \\\"count\\\": 2, \\\"total\\\": 2, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.4226}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"llama31-random-s123\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:52:25.749Z\", \"updated_at\": \"2026-05-16T12:53:57.052Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --output_dir output/llama31-random-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"277565\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-random-s123.log\", \"submitted_at\": \"2026-05-16T12:52:25.330Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 123}, \"hypothesis\": \"Cross-model: LLaMA Random s123 - 3rd seed for 3-seed cross-model validation\"}, \"llama31-taxei-s123\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:52:24.059Z\", \"updated_at\": \"2026-05-16T12:53:54.498Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct --dataset data/mini_pipeline_v4/sft_taxei_v4.jsonl --output_dir output/llama31-taxei-s123 --lora_rank 16 --num_train_epochs 3 --per_device_train_batch_size 4 --gradient_accumulation_steps 2 --learning_rate 1e-4 --max_length 4096 --seed 123 --data_seed 123 --logging_steps 10 --gradient_checkpointing true --bf16 true --save_strategy epoch\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"277419\", \"log_path\": \"~/runs/tax_error_inject_agent/llama31-taxei-s123.log\", \"submitted_at\": \"2026-05-16T12:52:23.670Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 123}, \"hypothesis\": \"Cross-model: LLaMA TaxEI s123 - 3rd seed for 3-seed cross-model validation\"}}, \"count\": 2, \"total\": 2, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4226}}"
    }
  },
  "sourceToolAssistantUUID": "e7cb726f-c6cb-4161-8118-ba19618dc9f3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 18 · 2026-05-16T14:53:40.651Z_

<details open><summary>🔧 Tool call — Agent · `toolu_01BbmLXayvRWQ5YLrpnBLT8u`</summary>

```json
{
  "description": "Extract llama31 registry data",
  "prompt": "I need to extract all experiments with IDs starting with \"llama31\" from a large JSON file. The file is at:\n/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt\n\nThe file has schema: {result: string} where result is a JSON string containing experiment data.\n\nI need ALL experiments whose ID starts with \"llama31\" — extract their full details including: status, metrics, spec (seed, model, data_path), hypothesis, conclusion, and any eval results.\n\nAlso extract any experiments with \"qwen\" in the ID that have metrics/eval data for comparison.\n\nUse jq or python to parse. Report the extracted data verbatim — I need exact numbers.",
  "subagent_type": "general-purpose"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "57d54223-a1cd-4bde-af6c-c1d8a84c67ab",
  "isSidechain": false,
  "requestId": "req_011Cb6SPnYxYtzP3seYF4AfL",
  "type": "assistant",
  "uuid": "d09aaea0-d388-4d9b-b15d-34ea2e61f111",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011rE9iyaJhxu4duja3rGNq2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1862,
      "cache_read_input_tokens": 24940,
      "output_tokens": 322,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1862,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 322,
          "cache_read_input_tokens": 24940,
          "cache_creation_input_tokens": 1862,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1862
          },
          "type": "message"
        }
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

_source line 19 · 2026-05-16T14:56:14.370Z_

<details><summary>↩ Tool result · `toolu_01BbmLXayvRWQ5YLrpnBLT8u`</summary>

```text
Here is the complete extracted data:

---

## ALL LLAMA31 EXPERIMENTS (18 total)

### llama31-random-s0
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 0
- **Data:** data/mini_pipeline_v4/sft_random_v4.jsonl (9031 samples)
- **Training Metrics:**
  - final_train_loss: 0.3368
  - epoch1_loss: 0.452, epoch2_loss: 0.238, epoch3_loss: 0.134
  - final_token_acc: 0.9357
  - train_steps: 3387, train_runtime_sec: 7622
  - peak_memory_gib: 30.74
- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s0/v0-20260516-171608/checkpoint-3387

### llama31-random-s0-eval
- **Status:** DONE | **Conclusion:** success
- **Eval type:** injected (47 ALFWorld episodes)
- **Metrics:**
  - recovery_rate: 0.745
  - detection_rate: 0.255
  - success_rate: 0.745
  - **By operator:**
    - C1_context_truncation: recovery=0.833, detection=0.083 (12 total, 10 recovered)
    - C4_observation_masking: recovery=0.727, detection=0.364 (11 total, 8 recovered)
    - P1_step_order_swap: recovery=0.667, detection=0.333 (12 total, 8 recovered)
    - P2_sub_goal_deletion: recovery=0.75, detection=0.25 (12 total, 9 recovered)

### llama31-random-s42
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 42
- **Data:** sft_random_v4.jsonl (9029 samples)
- **Hypothesis:** Cross-model generalizability: LLaMA-3.1-8B Random condition control
- **Training Metrics:**
  - train_loss: 0.3366
  - token_acc: 0.9364
  - train_steps: 3387, train_duration_s: 7622
- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387

### llama31-random-s42-clean
- **Status:** DONE | **Conclusion:** success
- **Eval type:** clean (47 ALFWorld tasks, no injection)
- **Metrics:**
  - success_rate: 0.766
  - total_episodes: 47

### llama31-random-s42-eval
- **Status:** DONE | **Conclusion:** success
- **Hypothesis:** Cross-model: LLaMA Random s42 eval -- random injection control on LLaMA
- **Eval type:** injected (47 episodes)
- **Metrics:**
  - recovery_rate: 0.766, recovery_count: 36/47
  - detection_rate: 0.298
  - **By operator (recovery):**
    - C1_context_truncation: 0.667
    - C4_observation_masking: 0.727
    - P1_step_order_swap: 0.917
    - P2_sub_goal_deletion: 0.75
  - **By operator (detection):**
    - C1_detection: 0.417
    - C4_detection: 0.364
    - P1_detection: 0.333
    - P2_detection: 0.083

### llama31-taxei-s0
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 0
- **Data:** sft_taxei_v4.jsonl (9029 samples)
- **Hypothesis:** Cross-model: LLaMA TaxEI s0 - 2nd seed for 3-seed cross-model validation
- **Training Metrics:**
  - final_train_loss: 0.32
  - final_token_acc: 0.88
  - train_steps: 3387
- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387

### llama31-taxei-s0-clean
- **Status:** DONE | **Conclusion:** success
- **Eval type:** clean (47 episodes)
- **Metrics:**
  - success_rate: 0.766
  - total_episodes: 47

### llama31-taxei-s0-eval
- **Status:** DONE | **Conclusion:** success
- **Hypothesis:** Cross-model: LLaMA TaxEI s0 injected eval -- does taxonomy injection help on LLaMA seed 0?
- **Eval type:** injected (47 episodes)
- **Metrics:**
  - recovery_rate: 0.745
  - success_rate: 0.745
  - total_episodes: 47

### llama31-taxei-s42
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 42
- **Data:** sft_taxei_v4.jsonl (9029 samples)
- **Hypothesis:** Cross-model generalizability: LLaMA-3.1-8B TaxEI condition to verify Qwen3-8B findings transfer
- **Training Metrics:**
  - train_loss: 0.3366
  - token_acc: 0.9357
  - train_steps: 3387, train_duration_s: 7782
- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387

### llama31-taxei-s42-eval
- **Status:** DONE | **Conclusion:** success
- **Hypothesis:** Cross-model: LLaMA TaxEI s42 eval -- does taxonomy-guided injection help on LLaMA?
- **Eval type:** injected (47 episodes)
- **Metrics:**
  - recovery_rate: 0.745, recovery_count: 35/47
  - detection_rate: 0.298
  - **By operator (recovery):**
    - C1_context_truncation: 0.833
    - C4_observation_masking: 0.727
    - P1_step_order_swap: 0.583
    - P2_sub_goal_deletion: 0.833
  - **By operator (detection):**
    - C1_detection: 0.167
    - C4_detection: 0.364
    - P1_detection: 0.25
    - P2_detection: 0.417

### llama31-vanilla-s0
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 0
- **Data:** sft_vanilla_v4.jsonl (4358 samples)
- **Training Metrics:**
  - final_train_loss: 0.398
  - epoch1_loss: 0.481, epoch2_loss: 0.362, epoch3_loss: 0.273
  - final_token_acc: 0.909
  - train_runtime_sec: 4158.6
- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635

### llama31-vanilla-s0-clean
- **Status:** DONE | **Conclusion:** success
- **Eval type:** clean (47 episodes)
- **Metrics:**
  - success_rate: 0.723
  - total_episodes: 47

### llama31-vanilla-s0-eval
- **Status:** DONE | **Conclusion:** success
- **Hypothesis:** LLaMA-3.1-8B Vanilla s0 injected eval - cross-model validation seed 0
- **Eval type:** injected (47 episodes)
- **Metrics:**
  - recovery_rate: 0.745, recovery_count: 35/47
  - detection_rate: 0.277
  - **By operator:**
    - C1_context_truncation: recovery=0.667, detection=0.167
    - C4_observation_masking: recovery=0.727, detection=0.364
    - P1_step_order_swap: recovery=0.917, detection=0.333
    - P2_sub_goal_deletion: recovery=0.667, detection=0.25

### llama31-vanilla-s123
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 123
- **Data:** sft_vanilla_v4.jsonl (4358 samples)
- **Hypothesis:** Cross-model: LLaMA Vanilla s123 - 3rd seed for 3-seed cross-model validation
- **Training Metrics:**
  - train_loss: 0.4, final_loss: 0.254
  - token_acc: 0.894
  - steps: 1635, epochs: 3, runtime_seconds: 4234
  - memory_gib: 29.85

### llama31-vanilla-s123-clean
- **Status:** DONE | **Conclusion:** success
- **Eval type:** clean (47 episodes)
- **Metrics:**
  - success_rate: 0.723
  - total_episodes: 47
  - **By task type:**
    - look_at_obj_in_light: 0.833
    - pick_and_place_simple: 0.625
    - pick_clean_then_place_in_recep: 0.545
    - pick_cool_then_place_in_recep: 0.571
    - pick_heat_then_place_in_recep: 1.0
    - pick_two_obj_and_place: 0.857

### llama31-vanilla-s42
- **Status:** DONE | **Conclusion:** success
- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 42
- **Data:** sft_vanilla_v4.jsonl (9029 samples)
- **Hypothesis:** Cross-model generalizability: LLaMA-3.1-8B Vanilla baseline
- **Training Metrics:**
  - train_loss: 0.40025
  - token_acc: 0.9067
  - train_steps: 1635, train_duration_s: 4157
- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635

### llama31-vanilla-s42-clean
- **Status:** DONE | **Conclusion:** success
- **Eval type:** clean (47 episodes)
- **Metrics:**
  - success_rate: 0.723
  - total_episodes: 47

### llama31-vanilla-s42-eval
- **Status:** DONE | **Conclusion:** success
- **Hypothesis:** LLaMA-3.1-8B Vanilla s42 injected eval - cross-model baseline
- **Eval type:** injected (47 episodes)
- **Metrics:**
  - recovery_rate: 0.745, recovery_count: 35/47
  - detection_rate: 0.213
  - **By operator (recovery):**
    - C1_context_truncation: 0.75
    - C4_observation_masking: 0.727
    - P1_step_order_swap: 0.75
    - P2_sub_goal_deletion: 0.75

---

## QWEN3-8B EXPERIMENTS WITH EVAL METRICS (30 total)

### eval-rp-s0 (Qwen3-8B TaxEI-RP s0)
- recovery_rate: 0.468, detection_rate: 0, episodes: 47, recovered: 22

### eval-rp-s1 (Qwen3-8B TaxEI-RP s1)
- recovery_rate: 0.489, detection_rate: 0, episodes: 47, recovered: 23

### eval-rp-s123 (Qwen3-8B TaxEI-RP s123)
- recovery_rate: 0.574, detection_rate: 0, episodes: 47, recovered: 27

### eval-rp-s42 (Qwen3-8B TaxEI-RP s42)
- recovery_rate: 0.383, recovery_count: 18/47, detection_rate: 0
- C1: 0.5, C4: 0.273, P1: 0.5, P2: 0.25

### eval-rp-s7 (Qwen3-8B TaxEI-RP s7)
- recovery_rate: 0.596, recovery_count: 28/47, detection_rate: 0

### recovery-random-s1 (Qwen3-8B + mini_random_sft_v4_seed1)
- recovery_rate: 0.511, detection_rate: 0, total_episodes: 47

### recovery-random-s7 (Qwen3-8B + mini_random_sft_v4_seed7)
- recovery_rate: 0.532, detection_rate: 0, total_episodes: 47

### recovery-taxei-s1 (Qwen3-8B + TaxEI LoRA s1)
- recovery_rate: 0.617, recovery_count: 29/47, detection_rate: 0
- C1: 0.75, C4: 0.636, P1: 0.583, P2: 0.5

### recovery-taxei-s7 (Qwen3-8B + TaxEI s7 LoRA)
- recovery_rate: 0.574, detection_rate: 0, total_episodes: 47

### recovery-vanilla-s1 (Qwen3-8B + Vanilla LoRA s1)
- recovery_rate: 0.66, recovery_count: 31/47, detection_rate: 0
- C1: 0.667, C4: 0.545, P1: 0.667, P2: 0.75

### recovery-vanilla-s7 (Qwen3-8B + Vanilla LoRA s7)
- recovery_rate: 0.745, recovery_count: 35/47, detection_rate: 0
- C1: 0.75, C4: 0.727, P1: 0.75, P2: 0.75

### v4-random-fixed-inject10-s0-eval-r3 (Qwen3-8B, random 10% inject, s0)
- success_rate: 0.66 (31/47, clean eval)

### v4-random-fixed-inject10-s1-eval (Qwen3-8B, random 10% inject, s1)
- success_rate: 0.681 (32/47, clean eval)

### v4-random-fixed-inject10-s123-eval (Qwen3-8B, random 10% inject, s123)
- success_rate: 0.553 (26/47, clean eval)

### v4-random-fixed-inject10-s7-eval (Qwen3-8B, random 10% inject, s7)
- success_rate: 0.617 (29/47, clean eval)

### v4-random-fixed-inject50-s1-eval (Qwen3-8B, random 50% inject, s1)
- success_rate: 0.702 (33/47, clean eval)

### v4-random-fixed-inject50-s7-eval (Qwen3-8B, random 50% inject, s7)
- success_rate: 0.468 (22/47, clean eval)

### v4-random-recovery-eval (Qwen3-8B + random SFT v4, s42, injected)
- recovery_rate: 0.638, detection_rate: 0, successes: 30/47

### v4-random-recovery-eval-s0 (Qwen3-8B + Random LoRA s0, injected)
- recovery_rate: 0.553, detection_rate: 0, total_episodes: 47
- C1: 0.583 (7/12), C4: 0.545 (6/11), P1: 0.583 (7/12), P2: 0.5 (6/12)

### v4-random-recovery-eval-s123 (Qwen3-8B + Random LoRA s123, injected)
- recovery_rate: 0.66, detection_rate: 0, total_episodes: 47
- C1: 0.75 (9/12), P2: 0.75 (9/12), P1: 0.583 (7/12), C4: 0.545 (6/11)

### v4-random-seed7-eval (Qwen3-8B + random SFT seed=7, clean)
- success_rate: 0.553 (26/47)

### v4-taxei-fixed-inject10-s1-eval-r2 (Qwen3-8B, taxei 10% inject, s1)
- success_rate: 0.511 (24/47, clean eval)

### v4-taxei-fixed-inject10-s123-eval-r3 (Qwen3-8B, taxei 10% inject, s123)
- success_rate: 0.553 (26/47, clean eval)

### v4-taxei-fixed-inject10-s7-eval (Qwen3-8B, taxei 10% inject, s7)
- success_rate: 0.681 (32/47, clean eval)

### v4-taxei-fixed-inject50-s1-eval (Qwen3-8B, taxei 50% inject, s1)
- success_rate: 0.638 (30/47, clean eval)

### v4-taxei-fixed-inject50-s7-eval (Qwen3-8B, taxei 50% inject, s7)
- success_rate: 0.553 (26/47, clean eval)

### v4-taxei-recovery-eval (Qwen3-8B + TaxEI LoRA v4, s42, injected)
- **Conclusion: negative**
- recovery_rate: 0.596, detection_rate: 0, successes: 28/47

### v4-taxei-recovery-eval-r2 (Qwen3-8B + TaxEI LoRA v4, s42, injected retry)
- recovery_rate: 0.596, detection_rate: 0, total_episodes: 47
- C1: 0.667 (8/12), C4: 0.636 (7/11), P1: 0.583 (7/12), P2: 0.5 (6/12)

### v4-taxei-seed7-eval (Qwen3-8B + TaxEI v4 seed=7, clean)
- success_rate: 0.617 (29/47)

### v4-vanilla-recovery-eval (Qwen3-8B + Vanilla v4, s42, injected)
- recovery_rate: 0.617, detection_rate: 0, successes: 29/47
- C1: 0.75 (9/12), C4: 0.545 (6/11), P1: 0.583 (7/12), P2: 0.583 (7/12)

---

## Key Comparative Observations

**LLaMA-3.1-8B (llama31) injected eval recovery rates:**
| Condition | s0 | s42 | Mean |
|-----------|-----|------|------|
| Vanilla | 0.745 | 0.745 | 0.745 |
| TaxEI | 0.745 | 0.745 | 0.745 |
| Random | 0.745 | 0.766 | 0.756 |

**LLaMA-3.1-8B detection rates:**
| Condition | s0 | s42 |
|-----------|-----|------|
| Vanilla | 0.277 | 0.213 |
| TaxEI | -- | 0.298 |
| Random | 0.255 | 0.298 |

**LLaMA-3.1-8B clean eval success rates:**
| Condition | s0 | s42 | s123 |
|-----------|-----|------|------|
| Vanilla | 0.723 | 0.723 | 0.723 |
| TaxEI | 0.766 | -- | -- |
| Random | -- | 0.766 | -- |

**Qwen3-8B injected eval recovery rates (for comparison):**
| Condition | s42 | s0 | s1 | s7 | s123 |
|-----------|------|-----|-----|-----|------|
| Vanilla | 0.617 | -- | 0.66 | 0.745 | -- |
| TaxEI | 0.596 | -- | 0.617 | 0.574 | -- |
| Random | 0.638 | 0.553 | 0.511 | 0.532 | 0.66 |
| TaxEI-RP | 0.383 | 0.468 | 0.489 | 0.596 | 0.574 |

Notable: LLaMA-3.1-8B shows uniformly high recovery (~0.745) across all conditions with non-zero detection rates (0.21-0.30), while Qwen3-8B shows more variance (0.38-0.75) with zero detection rate in most cases. The LLaMA results suggest the larger/newer model already has strong inherent resilience, making condition differences less distinguishable.

agentId: a1b20f795e02ae461 (use SendMessage with to: 'a1b20f795e02ae461' to continue this agent)
&lt;usage>total_tokens: 69349
tool_uses: 12
duration_ms: 153714&lt;/usage>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d09aaea0-d388-4d9b-b15d-34ea2e61f111",
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "e92fbbbe-60fb-48c4-97c2-1616f39af084",
  "toolUseResult": {
    "status": "completed",
    "prompt": "I need to extract all experiments with IDs starting with \"llama31\" from a large JSON file. The file is at:\n/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent/ae491a69-2268-4f52-bbd5-112d75ec9c55/tool-results/mcp-agent-ml-research-read_registry-1778943212143.txt\n\nThe file has schema: {result: string} where result is a JSON string containing experiment data.\n\nI need ALL experiments whose ID starts with \"llama31\" — extract their full details including: status, metrics, spec (seed, model, data_path), hypothesis, conclusion, and any eval results.\n\nAlso extract any experiments with \"qwen\" in the ID that have metrics/eval data for comparison.\n\nUse jq or python to parse. Report the extracted data verbatim — I need exact numbers.",
    "agentId": "a1b20f795e02ae461",
    "agentType": "general-purpose",
    "content": [
      {
        "type": "text",
        "text": "Here is the complete extracted data:\n\n---\n\n## ALL LLAMA31 EXPERIMENTS (18 total)\n\n### llama31-random-s0\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 0\n- **Data:** data/mini_pipeline_v4/sft_random_v4.jsonl (9031 samples)\n- **Training Metrics:**\n  - final_train_loss: 0.3368\n  - epoch1_loss: 0.452, epoch2_loss: 0.238, epoch3_loss: 0.134\n  - final_token_acc: 0.9357\n  - train_steps: 3387, train_runtime_sec: 7622\n  - peak_memory_gib: 30.74\n- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s0/v0-20260516-171608/checkpoint-3387\n\n### llama31-random-s0-eval\n- **Status:** DONE | **Conclusion:** success\n- **Eval type:** injected (47 ALFWorld episodes)\n- **Metrics:**\n  - recovery_rate: 0.745\n  - detection_rate: 0.255\n  - success_rate: 0.745\n  - **By operator:**\n    - C1_context_truncation: recovery=0.833, detection=0.083 (12 total, 10 recovered)\n    - C4_observation_masking: recovery=0.727, detection=0.364 (11 total, 8 recovered)\n    - P1_step_order_swap: recovery=0.667, detection=0.333 (12 total, 8 recovered)\n    - P2_sub_goal_deletion: recovery=0.75, detection=0.25 (12 total, 9 recovered)\n\n### llama31-random-s42\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 42\n- **Data:** sft_random_v4.jsonl (9029 samples)\n- **Hypothesis:** Cross-model generalizability: LLaMA-3.1-8B Random condition control\n- **Training Metrics:**\n  - train_loss: 0.3366\n  - token_acc: 0.9364\n  - train_steps: 3387, train_duration_s: 7622\n- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-random-s42/v0-20260516-142300/checkpoint-3387\n\n### llama31-random-s42-clean\n- **Status:** DONE | **Conclusion:** success\n- **Eval type:** clean (47 ALFWorld tasks, no injection)\n- **Metrics:**\n  - success_rate: 0.766\n  - total_episodes: 47\n\n### llama31-random-s42-eval\n- **Status:** DONE | **Conclusion:** success\n- **Hypothesis:** Cross-model: LLaMA Random s42 eval -- random injection control on LLaMA\n- **Eval type:** injected (47 episodes)\n- **Metrics:**\n  - recovery_rate: 0.766, recovery_count: 36/47\n  - detection_rate: 0.298\n  - **By operator (recovery):**\n    - C1_context_truncation: 0.667\n    - C4_observation_masking: 0.727\n    - P1_step_order_swap: 0.917\n    - P2_sub_goal_deletion: 0.75\n  - **By operator (detection):**\n    - C1_detection: 0.417\n    - C4_detection: 0.364\n    - P1_detection: 0.333\n    - P2_detection: 0.083\n\n### llama31-taxei-s0\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 0\n- **Data:** sft_taxei_v4.jsonl (9029 samples)\n- **Hypothesis:** Cross-model: LLaMA TaxEI s0 - 2nd seed for 3-seed cross-model validation\n- **Training Metrics:**\n  - final_train_loss: 0.32\n  - final_token_acc: 0.88\n  - train_steps: 3387\n- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s0/v1-20260516-181826/checkpoint-3387\n\n### llama31-taxei-s0-clean\n- **Status:** DONE | **Conclusion:** success\n- **Eval type:** clean (47 episodes)\n- **Metrics:**\n  - success_rate: 0.766\n  - total_episodes: 47\n\n### llama31-taxei-s0-eval\n- **Status:** DONE | **Conclusion:** success\n- **Hypothesis:** Cross-model: LLaMA TaxEI s0 injected eval -- does taxonomy injection help on LLaMA seed 0?\n- **Eval type:** injected (47 episodes)\n- **Metrics:**\n  - recovery_rate: 0.745\n  - success_rate: 0.745\n  - total_episodes: 47\n\n### llama31-taxei-s42\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 42\n- **Data:** sft_taxei_v4.jsonl (9029 samples)\n- **Hypothesis:** Cross-model generalizability: LLaMA-3.1-8B TaxEI condition to verify Qwen3-8B findings transfer\n- **Training Metrics:**\n  - train_loss: 0.3366\n  - token_acc: 0.9357\n  - train_steps: 3387, train_duration_s: 7782\n- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-taxei-s42/v0-20260516-142258/checkpoint-3387\n\n### llama31-taxei-s42-eval\n- **Status:** DONE | **Conclusion:** success\n- **Hypothesis:** Cross-model: LLaMA TaxEI s42 eval -- does taxonomy-guided injection help on LLaMA?\n- **Eval type:** injected (47 episodes)\n- **Metrics:**\n  - recovery_rate: 0.745, recovery_count: 35/47\n  - detection_rate: 0.298\n  - **By operator (recovery):**\n    - C1_context_truncation: 0.833\n    - C4_observation_masking: 0.727\n    - P1_step_order_swap: 0.583\n    - P2_sub_goal_deletion: 0.833\n  - **By operator (detection):**\n    - C1_detection: 0.167\n    - C4_detection: 0.364\n    - P1_detection: 0.25\n    - P2_detection: 0.417\n\n### llama31-vanilla-s0\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 0\n- **Data:** sft_vanilla_v4.jsonl (4358 samples)\n- **Training Metrics:**\n  - final_train_loss: 0.398\n  - epoch1_loss: 0.481, epoch2_loss: 0.362, epoch3_loss: 0.273\n  - final_token_acc: 0.909\n  - train_runtime_sec: 4158.6\n- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s0/v0-20260516-171603/checkpoint-1635\n\n### llama31-vanilla-s0-clean\n- **Status:** DONE | **Conclusion:** success\n- **Eval type:** clean (47 episodes)\n- **Metrics:**\n  - success_rate: 0.723\n  - total_episodes: 47\n\n### llama31-vanilla-s0-eval\n- **Status:** DONE | **Conclusion:** success\n- **Hypothesis:** LLaMA-3.1-8B Vanilla s0 injected eval - cross-model validation seed 0\n- **Eval type:** injected (47 episodes)\n- **Metrics:**\n  - recovery_rate: 0.745, recovery_count: 35/47\n  - detection_rate: 0.277\n  - **By operator:**\n    - C1_context_truncation: recovery=0.667, detection=0.167\n    - C4_observation_masking: recovery=0.727, detection=0.364\n    - P1_step_order_swap: recovery=0.917, detection=0.333\n    - P2_sub_goal_deletion: recovery=0.667, detection=0.25\n\n### llama31-vanilla-s123\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 123\n- **Data:** sft_vanilla_v4.jsonl (4358 samples)\n- **Hypothesis:** Cross-model: LLaMA Vanilla s123 - 3rd seed for 3-seed cross-model validation\n- **Training Metrics:**\n  - train_loss: 0.4, final_loss: 0.254\n  - token_acc: 0.894\n  - steps: 1635, epochs: 3, runtime_seconds: 4234\n  - memory_gib: 29.85\n\n### llama31-vanilla-s123-clean\n- **Status:** DONE | **Conclusion:** success\n- **Eval type:** clean (47 episodes)\n- **Metrics:**\n  - success_rate: 0.723\n  - total_episodes: 47\n  - **By task type:**\n    - look_at_obj_in_light: 0.833\n    - pick_and_place_simple: 0.625\n    - pick_clean_then_place_in_recep: 0.545\n    - pick_cool_then_place_in_recep: 0.571\n    - pick_heat_then_place_in_recep: 1.0\n    - pick_two_obj_and_place: 0.857\n\n### llama31-vanilla-s42\n- **Status:** DONE | **Conclusion:** success\n- **Model:** Meta-Llama-3.1-8B-Instruct | **Seed:** 42\n- **Data:** sft_vanilla_v4.jsonl (9029 samples)\n- **Hypothesis:** Cross-model generalizability: LLaMA-3.1-8B Vanilla baseline\n- **Training Metrics:**\n  - train_loss: 0.40025\n  - token_acc: 0.9067\n  - train_steps: 1635, train_duration_s: 4157\n- **Checkpoint:** /root/autodl-tmp/tax_error_inject_agent/output/llama31-vanilla-s42/v0-20260516-143227/checkpoint-1635\n\n### llama31-vanilla-s42-clean\n- **Status:** DONE | **Conclusion:** success\n- **Eval type:** clean (47 episodes)\n- **Metrics:**\n  - success_rate: 0.723\n  - total_episodes: 47\n\n### llama31-vanilla-s42-eval\n- **Status:** DONE | **Conclusion:** success\n- **Hypothesis:** LLaMA-3.1-8B Vanilla s42 injected eval - cross-model baseline\n- **Eval type:** injected (47 episodes)\n- **Metrics:**\n  - recovery_rate: 0.745, recovery_count: 35/47\n  - detection_rate: 0.213\n  - **By operator (recovery):**\n    - C1_context_truncation: 0.75\n    - C4_observation_masking: 0.727\n    - P1_step_order_swap: 0.75\n    - P2_sub_goal_deletion: 0.75\n\n---\n\n## QWEN3-8B EXPERIMENTS WITH EVAL METRICS (30 total)\n\n### eval-rp-s0 (Qwen3-8B TaxEI-RP s0)\n- recovery_rate: 0.468, detection_rate: 0, episodes: 47, recovered: 22\n\n### eval-rp-s1 (Qwen3-8B TaxEI-RP s1)\n- recovery_rate: 0.489, detection_rate: 0, episodes: 47, recovered: 23\n\n### eval-rp-s123 (Qwen3-8B TaxEI-RP s123)\n- recovery_rate: 0.574, detection_rate: 0, episodes: 47, recovered: 27\n\n### eval-rp-s42 (Qwen3-8B TaxEI-RP s42)\n- recovery_rate: 0.383, recovery_count: 18/47, detection_rate: 0\n- C1: 0.5, C4: 0.273, P1: 0.5, P2: 0.25\n\n### eval-rp-s7 (Qwen3-8B TaxEI-RP s7)\n- recovery_rate: 0.596, recovery_count: 28/47, detection_rate: 0\n\n### recovery-random-s1 (Qwen3-8B + mini_random_sft_v4_seed1)\n- recovery_rate: 0.511, detection_rate: 0, total_episodes: 47\n\n### recovery-random-s7 (Qwen3-8B + mini_random_sft_v4_seed7)\n- recovery_rate: 0.532, detection_rate: 0, total_episodes: 47\n\n### recovery-taxei-s1 (Qwen3-8B + TaxEI LoRA s1)\n- recovery_rate: 0.617, recovery_count: 29/47, detection_rate: 0\n- C1: 0.75, C4: 0.636, P1: 0.583, P2: 0.5\n\n### recovery-taxei-s7 (Qwen3-8B + TaxEI s7 LoRA)\n- recovery_rate: 0.574, detection_rate: 0, total_episodes: 47\n\n### recovery-vanilla-s1 (Qwen3-8B + Vanilla LoRA s1)\n- recovery_rate: 0.66, recovery_count: 31/47, detection_rate: 0\n- C1: 0.667, C4: 0.545, P1: 0.667, P2: 0.75\n\n### recovery-vanilla-s7 (Qwen3-8B + Vanilla LoRA s7)\n- recovery_rate: 0.745, recovery_count: 35/47, detection_rate: 0\n- C1: 0.75, C4: 0.727, P1: 0.75, P2: 0.75\n\n### v4-random-fixed-inject10-s0-eval-r3 (Qwen3-8B, random 10% inject, s0)\n- success_rate: 0.66 (31/47, clean eval)\n\n### v4-random-fixed-inject10-s1-eval (Qwen3-8B, random 10% inject, s1)\n- success_rate: 0.681 (32/47, clean eval)\n\n### v4-random-fixed-inject10-s123-eval (Qwen3-8B, random 10% inject, s123)\n- success_rate: 0.553 (26/47, clean eval)\n\n### v4-random-fixed-inject10-s7-eval (Qwen3-8B, random 10% inject, s7)\n- success_rate: 0.617 (29/47, clean eval)\n\n### v4-random-fixed-inject50-s1-eval (Qwen3-8B, random 50% inject, s1)\n- success_rate: 0.702 (33/47, clean eval)\n\n### v4-random-fixed-inject50-s7-eval (Qwen3-8B, random 50% inject, s7)\n- success_rate: 0.468 (22/47, clean eval)\n\n### v4-random-recovery-eval (Qwen3-8B + random SFT v4, s42, injected)\n- recovery_rate: 0.638, detection_rate: 0, successes: 30/47\n\n### v4-random-recovery-eval-s0 (Qwen3-8B + Random LoRA s0, injected)\n- recovery_rate: 0.553, detection_rate: 0, total_episodes: 47\n- C1: 0.583 (7/12), C4: 0.545 (6/11), P1: 0.583 (7/12), P2: 0.5 (6/12)\n\n### v4-random-recovery-eval-s123 (Qwen3-8B + Random LoRA s123, injected)\n- recovery_rate: 0.66, detection_rate: 0, total_episodes: 47\n- C1: 0.75 (9/12), P2: 0.75 (9/12), P1: 0.583 (7/12), C4: 0.545 (6/11)\n\n### v4-random-seed7-eval (Qwen3-8B + random SFT seed=7, clean)\n- success_rate: 0.553 (26/47)\n\n### v4-taxei-fixed-inject10-s1-eval-r2 (Qwen3-8B, taxei 10% inject, s1)\n- success_rate: 0.511 (24/47, clean eval)\n\n### v4-taxei-fixed-inject10-s123-eval-r3 (Qwen3-8B, taxei 10% inject, s123)\n- success_rate: 0.553 (26/47, clean eval)\n\n### v4-taxei-fixed-inject10-s7-eval (Qwen3-8B, taxei 10% inject, s7)\n- success_rate: 0.681 (32/47, clean eval)\n\n### v4-taxei-fixed-inject50-s1-eval (Qwen3-8B, taxei 50% inject, s1)\n- success_rate: 0.638 (30/47, clean eval)\n\n### v4-taxei-fixed-inject50-s7-eval (Qwen3-8B, taxei 50% inject, s7)\n- success_rate: 0.553 (26/47, clean eval)\n\n### v4-taxei-recovery-eval (Qwen3-8B + TaxEI LoRA v4, s42, injected)\n- **Conclusion: negative**\n- recovery_rate: 0.596, detection_rate: 0, successes: 28/47\n\n### v4-taxei-recovery-eval-r2 (Qwen3-8B + TaxEI LoRA v4, s42, injected retry)\n- recovery_rate: 0.596, detection_rate: 0, total_episodes: 47\n- C1: 0.667 (8/12), C4: 0.636 (7/11), P1: 0.583 (7/12), P2: 0.5 (6/12)\n\n### v4-taxei-seed7-eval (Qwen3-8B + TaxEI v4 seed=7, clean)\n- success_rate: 0.617 (29/47)\n\n### v4-vanilla-recovery-eval (Qwen3-8B + Vanilla v4, s42, injected)\n- recovery_rate: 0.617, detection_rate: 0, successes: 29/47\n- C1: 0.75 (9/12), C4: 0.545 (6/11), P1: 0.583 (7/12), P2: 0.583 (7/12)\n\n---\n\n## Key Comparative Observations\n\n**LLaMA-3.1-8B (llama31) injected eval recovery rates:**\n| Condition | s0 | s42 | Mean |\n|-----------|-----|------|------|\n| Vanilla | 0.745 | 0.745 | 0.745 |\n| TaxEI | 0.745 | 0.745 | 0.745 |\n| Random | 0.745 | 0.766 | 0.756 |\n\n**LLaMA-3.1-8B detection rates:**\n| Condition | s0 | s42 |\n|-----------|-----|------|\n| Vanilla | 0.277 | 0.213 |\n| TaxEI | -- | 0.298 |\n| Random | 0.255 | 0.298 |\n\n**LLaMA-3.1-8B clean eval success rates:**\n| Condition | s0 | s42 | s123 |\n|-----------|-----|------|------|\n| Vanilla | 0.723 | 0.723 | 0.723 |\n| TaxEI | 0.766 | -- | -- |\n| Random | -- | 0.766 | -- |\n\n**Qwen3-8B injected eval recovery rates (for comparison):**\n| Condition | s42 | s0 | s1 | s7 | s123 |\n|-----------|------|-----|-----|-----|------|\n| Vanilla | 0.617 | -- | 0.66 | 0.745 | -- |\n| TaxEI | 0.596 | -- | 0.617 | 0.574 | -- |\n| Random | 0.638 | 0.553 | 0.511 | 0.532 | 0.66 |\n| TaxEI-RP | 0.383 | 0.468 | 0.489 | 0.596 | 0.574 |\n\nNotable: LLaMA-3.1-8B shows uniformly high recovery (~0.745) across all conditions with non-zero detection rates (0.21-0.30), while Qwen3-8B shows more variance (0.38-0.75) with zero detection rate in most cases. The LLaMA results suggest the larger/newer model already has strong inherent resilience, making condition differences less distinguishable."
      }
    ],
    "totalDurationMs": 153714,
    "totalTokens": 69349,
    "totalToolUseCount": 12,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1278,
      "cache_read_input_tokens": 62366,
      "output_tokens": 5704,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1278
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 5704,
          "cache_read_input_tokens": 62366,
          "cache_creation_input_tokens": 1278,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1278,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 6,
      "searchCount": 0,
      "bashCount": 6,
      "editFileCount": 0,
      "linesAdded": 0,
      "linesRemoved": 0,
      "otherToolCount": 0
    }
  },
  "sourceToolAssistantUUID": "d09aaea0-d388-4d9b-b15d-34ea2e61f111",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 20_

```json
{
  "type": "last-prompt",
  "leafUuid": "e92fbbbe-60fb-48c4-97c2-1616f39af084",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Compile LLaMA cross-model validation results",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

### Assistant

_source line 22 · 2026-05-16T14:56:46.461Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the data I need. Let me also check if there's a llama31-taxei-s42-clean eval or llama31-random-s0-clean eval in the data. Looking at what was extracted:

LLaMA experiments found:
- llama31-vanilla-s42: train done, eval done (injected), clean done
- llama31-vanilla-s0: train done, eval done (injected), clean done
- llama31-vanilla-s123: train done, clean done (no injected eval yet? Let me check... no injected eval mentioned)


- llama31-taxei-s42: train done, eval done (injected), no clean mentioned
- llama31-taxei-s0: train done, eval done (injected), clean done
- llama31-taxei-s123: currently running
- llama31-random-s42: train done, eval done (injected), clean done
- llama31-random-s0: train done, eval done (injected), no clean mentioned
- llama31-random-s123: currently running

Now let me look more carefully at the actual training metrics to see what values I'm working with.

Looking at the training loss and token accuracy across all the models, the taxei and random variants are performing better than vanilla across the board. The taxei-s42 and random-s42 are showing particularly strong token accuracy around 0.936, while vanilla models are hovering around 0.89-0.91. The injected eval metrics show recovery rates around 0.745 for the vanilla models, and I need to see the full picture for the other variants. I'm noticing some gaps in the clean eval results—specifically missing entries for llama31-taxei-s42-clean and llama31-random-s0-clean. Let me cross-reference what was actually extracted to see which evaluations are still unaccounted for.

Looking at the vanilla-s123 experiments, the training and clean eval are both marked as done, but there's no injected eval listed yet, so that one appears to still be pending. The task notes mention that s123 for taxei and random are still training, so those would explain why their evals aren't complete.

Now I'm compiling the results into summary tables with the loss metrics across all seeds and methods. Looking at the clean eval results more carefully, I see vanilla completed across all seeds, TaxEI only has s0, and Random only has s42 — the missing ones for TaxEI and Random are probably still waiting for their evaluations to finish since only the s123 variants are currently running.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e92fbbbe-60fb-48c4-97c2-1616f39af084",
  "isSidechain": false,
  "requestId": "req_011Cb6SbiKJSoxuZKTBAfxYN",
  "type": "assistant",
  "uuid": "7545e5a7-2661-4e8e-bc25-4ddbd0269c41",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Paogrk2MJPXhfjydwQibq9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6103,
      "cache_read_input_tokens": 26802,
      "output_tokens": 3763,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6103,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3763,
          "cache_read_input_tokens": 26802,
          "cache_creation_input_tokens": 6103,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6103
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-16T14:56:46.555Z_

I have all the data. Now I'll compile the summary and write the artifact.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7545e5a7-2661-4e8e-bc25-4ddbd0269c41",
  "isSidechain": false,
  "requestId": "req_011Cb6SbiKJSoxuZKTBAfxYN",
  "type": "assistant",
  "uuid": "1871a677-1c55-45ed-87f8-5765cd375181",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Paogrk2MJPXhfjydwQibq9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6103,
      "cache_read_input_tokens": 26802,
      "output_tokens": 3763,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6103,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3763,
          "cache_read_input_tokens": 26802,
          "cache_creation_input_tokens": 6103,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6103
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-16T14:57:16.361Z_

<details open><summary>🔧 Tool call — Write · `toolu_01KkzLZpxiN8Zc9YkNNj9sFC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/llama_crossmodel_summary.md",
  "content": "# LLaMA-3.1-8B Cross-Model Validation Summary\n\n**Date:** 2026-05-16  \n**Purpose:** Validate Qwen3-8B negative result (TaxEI ≈ Random) on a second model architecture.\n\n---\n\n## 1. Training Metrics\n\n| Seed | Vanilla loss | TaxEI loss | Random loss |\n|------|-------------|------------|-------------|\n| s42  | 0.400 | 0.337 | 0.337 |\n| s0   | 0.398 | 0.320 | 0.337 |\n| s123 | 0.400 | (running) | (running) |\n\nNotes:\n- Vanilla trains on 4358 samples (clean only), TaxEI/Random on 9029 samples (clean + injected)\n- Loss difference reflects data composition, not model quality\n- Token accuracy: Vanilla ~0.90, TaxEI/Random ~0.93\n\n---\n\n## 2. Injected Eval — Recovery Rate (47 episodes, 4 error operators)\n\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | 74.5% | 74.5% | 76.6% |\n| s0   | 74.5% | 74.5% | 74.5% |\n| s123 | (pending) | (pending) | (pending) |\n| **Mean (s0+s42)** | **74.5%** | **74.5%** | **75.5%** |\n\nDetection rates (non-zero, unlike Qwen3-8B):\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | 21.3% | 29.8% | 29.8% |\n| s0   | 27.7% | — | 25.5% |\n\n---\n\n## 3. Clean Eval — Success Rate (47 episodes, no injection)\n\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | 72.3% | (not run) | 76.6% |\n| s0   | 72.3% | 76.6% | (not run) |\n| s123 | 72.3% | (pending) | (pending) |\n| **Mean** | **72.3%** | **76.6%** | **76.6%** |\n\n---\n\n## 4. Per-Operator Recovery Breakdown (Injected Eval)\n\n### s42\n| Operator | Vanilla | TaxEI | Random |\n|----------|---------|-------|--------|\n| C1_context_truncation | 75.0% | 83.3% | 66.7% |\n| C4_observation_masking | 72.7% | 72.7% | 72.7% |\n| P1_step_order_swap | 75.0% | 58.3% | 91.7% |\n| P2_sub_goal_deletion | 75.0% | 83.3% | 75.0% |\n\n### s0\n| Operator | Vanilla | TaxEI | Random |\n|----------|---------|-------|--------|\n| C1_context_truncation | 66.7% | — | 83.3% |\n| C4_observation_masking | 72.7% | — | 72.7% |\n| P1_step_order_swap | 91.7% | — | 66.7% |\n| P2_sub_goal_deletion | 66.7% | — | 75.0% |\n\n---\n\n## 5. LLaMA vs Qwen3-8B Comparison\n\n### Key Metrics Side-by-Side\n\n| Metric | Qwen3-8B (5-seed) | LLaMA-3.1-8B (2-seed) |\n|--------|-------------------|------------------------|\n| **Vanilla recovery** | 67.3 ± 4.7% | 74.5 ± 0.0% |\n| **TaxEI recovery** | 58.3 ± 6.5% | 74.5 ± 0.0% |\n| **Random recovery** | 58.3 ± 8.7% | 75.5 ± 1.1% |\n| **Injection penalty** | ~9pp (67.3→58.3) | **None** (74.5→74.5) |\n| **Detection rate** | 0% (all seeds) | 21-30% |\n| **Clean success (Vanilla)** | ~65% | 72.3% |\n\n### Critical Findings\n\n1. **No injection penalty on LLaMA:** All three conditions achieve ~74.5% recovery — injection training neither helps nor hurts. On Qwen3-8B, injection training *reduced* performance by ~9pp.\n\n2. **All conditions converge:** LLaMA shows near-zero variance across conditions (74.5% vs 74.5% vs 76.6%), suggesting the model's baseline capability dominates over training signal differences.\n\n3. **Non-zero detection on LLaMA:** LLaMA detects errors 21-30% of the time (Qwen3-8B: 0%), indicating stronger intrinsic error awareness regardless of training condition.\n\n4. **Higher absolute performance:** LLaMA outperforms Qwen3-8B across the board (+7-16pp recovery, +7pp clean success), consistent with it being a stronger instruction-following model.\n\n5. **Strengthens negative result:** The cross-model validation confirms TaxEI provides no advantage — but for a *different reason* than Qwen3-8B:\n   - Qwen3-8B: TaxEI = Random (both hurt vs Vanilla)\n   - LLaMA: TaxEI = Random = Vanilla (nothing helps because baseline is already strong)\n\n---\n\n## 6. Pending Experiments\n\n| Experiment | Status | ETA |\n|-----------|--------|-----|\n| llama31-taxei-s123 | Training | ~2h |\n| llama31-random-s123 | Training | ~2h |\n| llama31-vanilla-s123-eval (injected) | Not submitted | After training completes |\n| llama31-taxei-s42-clean | Not submitted | — |\n| llama31-random-s0-clean | Not submitted | — |\n\n---\n\n## 7. Implications for Paper\n\nThe LLaMA cross-model validation provides a **second mechanism** supporting the negative result:\n- **Qwen3-8B story:** TaxEI doesn't outperform Random injection (both degrade vs Vanilla)\n- **LLaMA story:** Model already resilient — no injection method adds value when baseline is strong\n\nTogether these argue that taxonomy-guided error injection is not a robust training strategy: it fails to help weak models (Qwen) and is unnecessary for strong ones (LLaMA).\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1871a677-1c55-45ed-87f8-5765cd375181",
  "isSidechain": false,
  "requestId": "req_011Cb6SbiKJSoxuZKTBAfxYN",
  "type": "assistant",
  "uuid": "2de87046-f680-4cd0-95b2-329e75245121",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Paogrk2MJPXhfjydwQibq9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6103,
      "cache_read_input_tokens": 26802,
      "output_tokens": 3763,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6103,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3763,
          "cache_read_input_tokens": 26802,
          "cache_creation_input_tokens": 6103,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6103
          },
          "type": "message"
        }
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

_source line 25 · 2026-05-16T14:57:16.389Z_

<details><summary>↩ Tool result · `toolu_01KkzLZpxiN8Zc9YkNNj9sFC`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/llama_crossmodel_summary.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2de87046-f680-4cd0-95b2-329e75245121",
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "3f6195f0-e94f-425c-9e71-ae8369e01ee6",
  "toolUseResult": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/llama_crossmodel_summary.md",
    "content": "# LLaMA-3.1-8B Cross-Model Validation Summary\n\n**Date:** 2026-05-16  \n**Purpose:** Validate Qwen3-8B negative result (TaxEI ≈ Random) on a second model architecture.\n\n---\n\n## 1. Training Metrics\n\n| Seed | Vanilla loss | TaxEI loss | Random loss |\n|------|-------------|------------|-------------|\n| s42  | 0.400 | 0.337 | 0.337 |\n| s0   | 0.398 | 0.320 | 0.337 |\n| s123 | 0.400 | (running) | (running) |\n\nNotes:\n- Vanilla trains on 4358 samples (clean only), TaxEI/Random on 9029 samples (clean + injected)\n- Loss difference reflects data composition, not model quality\n- Token accuracy: Vanilla ~0.90, TaxEI/Random ~0.93\n\n---\n\n## 2. Injected Eval — Recovery Rate (47 episodes, 4 error operators)\n\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | 74.5% | 74.5% | 76.6% |\n| s0   | 74.5% | 74.5% | 74.5% |\n| s123 | (pending) | (pending) | (pending) |\n| **Mean (s0+s42)** | **74.5%** | **74.5%** | **75.5%** |\n\nDetection rates (non-zero, unlike Qwen3-8B):\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | 21.3% | 29.8% | 29.8% |\n| s0   | 27.7% | — | 25.5% |\n\n---\n\n## 3. Clean Eval — Success Rate (47 episodes, no injection)\n\n| Seed | Vanilla | TaxEI | Random |\n|------|---------|-------|--------|\n| s42  | 72.3% | (not run) | 76.6% |\n| s0   | 72.3% | 76.6% | (not run) |\n| s123 | 72.3% | (pending) | (pending) |\n| **Mean** | **72.3%** | **76.6%** | **76.6%** |\n\n---\n\n## 4. Per-Operator Recovery Breakdown (Injected Eval)\n\n### s42\n| Operator | Vanilla | TaxEI | Random |\n|----------|---------|-------|--------|\n| C1_context_truncation | 75.0% | 83.3% | 66.7% |\n| C4_observation_masking | 72.7% | 72.7% | 72.7% |\n| P1_step_order_swap | 75.0% | 58.3% | 91.7% |\n| P2_sub_goal_deletion | 75.0% | 83.3% | 75.0% |\n\n### s0\n| Operator | Vanilla | TaxEI | Random |\n|----------|---------|-------|--------|\n| C1_context_truncation | 66.7% | — | 83.3% |\n| C4_observation_masking | 72.7% | — | 72.7% |\n| P1_step_order_swap | 91.7% | — | 66.7% |\n| P2_sub_goal_deletion | 66.7% | — | 75.0% |\n\n---\n\n## 5. LLaMA vs Qwen3-8B Comparison\n\n### Key Metrics Side-by-Side\n\n| Metric | Qwen3-8B (5-seed) | LLaMA-3.1-8B (2-seed) |\n|--------|-------------------|------------------------|\n| **Vanilla recovery** | 67.3 ± 4.7% | 74.5 ± 0.0% |\n| **TaxEI recovery** | 58.3 ± 6.5% | 74.5 ± 0.0% |\n| **Random recovery** | 58.3 ± 8.7% | 75.5 ± 1.1% |\n| **Injection penalty** | ~9pp (67.3→58.3) | **None** (74.5→74.5) |\n| **Detection rate** | 0% (all seeds) | 21-30% |\n| **Clean success (Vanilla)** | ~65% | 72.3% |\n\n### Critical Findings\n\n1. **No injection penalty on LLaMA:** All three conditions achieve ~74.5% recovery — injection training neither helps nor hurts. On Qwen3-8B, injection training *reduced* performance by ~9pp.\n\n2. **All conditions converge:** LLaMA shows near-zero variance across conditions (74.5% vs 74.5% vs 76.6%), suggesting the model's baseline capability dominates over training signal differences.\n\n3. **Non-zero detection on LLaMA:** LLaMA detects errors 21-30% of the time (Qwen3-8B: 0%), indicating stronger intrinsic error awareness regardless of training condition.\n\n4. **Higher absolute performance:** LLaMA outperforms Qwen3-8B across the board (+7-16pp recovery, +7pp clean success), consistent with it being a stronger instruction-following model.\n\n5. **Strengthens negative result:** The cross-model validation confirms TaxEI provides no advantage — but for a *different reason* than Qwen3-8B:\n   - Qwen3-8B: TaxEI = Random (both hurt vs Vanilla)\n   - LLaMA: TaxEI = Random = Vanilla (nothing helps because baseline is already strong)\n\n---\n\n## 6. Pending Experiments\n\n| Experiment | Status | ETA |\n|-----------|--------|-----|\n| llama31-taxei-s123 | Training | ~2h |\n| llama31-random-s123 | Training | ~2h |\n| llama31-vanilla-s123-eval (injected) | Not submitted | After training completes |\n| llama31-taxei-s42-clean | Not submitted | — |\n| llama31-random-s0-clean | Not submitted | — |\n\n---\n\n## 7. Implications for Paper\n\nThe LLaMA cross-model validation provides a **second mechanism** supporting the negative result:\n- **Qwen3-8B story:** TaxEI doesn't outperform Random injection (both degrade vs Vanilla)\n- **LLaMA story:** Model already resilient — no injection method adds value when baseline is strong\n\nTogether these argue that taxonomy-guided error injection is not a robust training strategy: it fails to help weak models (Qwen) and is unnecessary for strong ones (LLaMA).\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  },
  "sourceToolAssistantUUID": "2de87046-f680-4cd0-95b2-329e75245121",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-16T14:57:22.593Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01Fev2xDAaw9g5QpuctX6iCn`</summary>

```json
{
  "name": "LLaMA-3.1-8B Cross-Model Validation Summary",
  "type": "report",
  "description": "Complete results table for LLaMA-3.1-8B cross-model validation: training metrics, injected eval recovery rates, clean eval success rates, per-operator breakdown, and comparison with Qwen3-8B findings.",
  "project": "tax_error_inject_agent",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/llama_crossmodel_summary.md",
  "tags": [
    "llama31",
    "cross-model",
    "results",
    "negative-result"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3f6195f0-e94f-425c-9e71-ae8369e01ee6",
  "isSidechain": false,
  "requestId": "req_011Cb6SgHRyd8ngK8Dhv4VJU",
  "type": "assistant",
  "uuid": "d4e1c308-ad18-4348-81b3-95d2fe52cee2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018PFqcEBZZFdEpi9CgEfPBi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3822,
      "cache_read_input_tokens": 32905,
      "output_tokens": 277,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3822,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 277,
          "cache_read_input_tokens": 32905,
          "cache_creation_input_tokens": 3822,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3822
          },
          "type": "message"
        }
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

_source line 27 · 2026-05-16T14:57:22.698Z_

<details><summary>↩ Tool result · `toolu_01Fev2xDAaw9g5QpuctX6iCn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260516_0dc6e0\", \"name\": \"LLaMA-3.1-8B Cross-Model Validation Summary\", \"type\": \"report\", \"description\": \"Complete results table for LLaMA-3.1-8B cross-model validation: training metrics, injected eval recovery rates, clean eval success rates, per-operator breakdown, and comparison with Qwen3-8B findings.\", \"path\": \"projects/tax_error_inject_agent/artifacts/_project/report/llama_crossmodel_summary.md\", \"url\": null, \"project\": \"tax_error_inject_agent\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-16T14:57:22.600477+00:00\", \"tags\": [\"llama31\", \"cross-model\", \"results\", \"negative-result\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d4e1c308-ad18-4348-81b3-95d2fe52cee2",
  "isSidechain": false,
  "promptId": "71dedd80-f604-403e-b956-0b1b8a8bce87",
  "type": "user",
  "uuid": "7be7b0f4-00fa-4a32-bd9c-e8ab361c5008",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260516_0dc6e0\\\", \\\"name\\\": \\\"LLaMA-3.1-8B Cross-Model Validation Summary\\\", \\\"type\\\": \\\"report\\\", \\\"description\\\": \\\"Complete results table for LLaMA-3.1-8B cross-model validation: training metrics, injected eval recovery rates, clean eval success rates, per-operator breakdown, and comparison with Qwen3-8B findings.\\\", \\\"path\\\": \\\"projects/tax_error_inject_agent/artifacts/_project/report/llama_crossmodel_summary.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"tax_error_inject_agent\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-16T14:57:22.600477+00:00\\\", \\\"tags\\\": [\\\"llama31\\\", \\\"cross-model\\\", \\\"results\\\", \\\"negative-result\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260516_0dc6e0\", \"name\": \"LLaMA-3.1-8B Cross-Model Validation Summary\", \"type\": \"report\", \"description\": \"Complete results table for LLaMA-3.1-8B cross-model validation: training metrics, injected eval recovery rates, clean eval success rates, per-operator breakdown, and comparison with Qwen3-8B findings.\", \"path\": \"projects/tax_error_inject_agent/artifacts/_project/report/llama_crossmodel_summary.md\", \"url\": null, \"project\": \"tax_error_inject_agent\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-16T14:57:22.600477+00:00\", \"tags\": [\"llama31\", \"cross-model\", \"results\", \"negative-result\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "d4e1c308-ad18-4348-81b3-95d2fe52cee2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 28 · 2026-05-16T14:57:29.801Z_

已完成。核心发现：

**LLaMA-3.1-8B (2-seed):** Vanilla=74.5%, TaxEI=74.5%, Random=75.5% — 三个条件完全收敛，无 injection penalty。

**与 Qwen3-8B 的关键差异：**
- Qwen3-8B: injection 训练降低性能 ~9pp（67.3→58.3），但 TaxEI≈Random
- LLaMA: 模型本身已足够强，任何 injection 方法都不增加价值（也不损害）
- LLaMA 有 21-30% detection rate（Qwen3-8B 为 0%）

**Pending:** s123 的 taxei 和 random 仍在训练中，另外 taxei-s42-clean 和 random-s0-clean 未提交。

Artifact 已注册：`art_20260516_0dc6e0`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7be7b0f4-00fa-4a32-bd9c-e8ab361c5008",
  "isSidechain": false,
  "requestId": "req_011Cb6SgkeqFrsiys3MRme91",
  "type": "assistant",
  "uuid": "4bdd911a-c594-4b81-861c-b36f51060d62",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016tUNyeKFSwSjz9EjooFyJK",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 593,
      "cache_read_input_tokens": 36727,
      "output_tokens": 263,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 593,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 263,
          "cache_read_input_tokens": 36727,
          "cache_creation_input_tokens": 593,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 593
          },
          "type": "message"
        }
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

_source line 29_

```json
{
  "type": "last-prompt",
  "leafUuid": "4bdd911a-c594-4b81-861c-b36f51060d62",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

### Runtime record

_source line 30_

```json
{
  "type": "ai-title",
  "aiTitle": "Compile LLaMA cross-model validation results",
  "sessionId": "ae491a69-2268-4f52-bbd5-112d75ec9c55"
}
```

---

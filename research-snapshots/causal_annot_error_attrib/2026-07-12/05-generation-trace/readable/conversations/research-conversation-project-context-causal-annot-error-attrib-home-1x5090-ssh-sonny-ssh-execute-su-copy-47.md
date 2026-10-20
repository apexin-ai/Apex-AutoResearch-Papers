# Research conversation: <project_context> # 项目: causal_annot_error_attrib ## 运行环境 - 服务器名: home-1x5090 - SSH 账户: sonny（调用 ssh_execute / submit_tr

**Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 111
- **Recorded user turns:** 1
- **Tool calls:** 31
- **Original source:** `logs/chats/exported-trajectories/account-2/e79c5c6a-c505-464a-beed-9ce58a792bcc.jsonl`
- **Structured JSON:** [`629469f9118dcd6c098d.json`](../../sessions/62/629469f9118dcd6c098d.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-24T06:35:20.033Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-24T06:35:20.033Z",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "content": "&lt;project_context>\n# 项目: causal_annot_error_attrib\n\n## 运行环境\n- 服务器名: home-1x5090\n- SSH 账户: sonny（调用 ssh_execute / submit_training_job 时传入 account=\"sonny\"）\n- SSH 连接命令: ssh implicit5638.xyfu.me  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /home/sonny/causal_annot_error_attrib\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n## 任务：全文斜体滥用修复 + 附录公式重复清理\n\n### 项目根目录\n`/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/`\n\n### Part 1: 斜体滥用修复\n\n通读 `docs/paper/` 下所有 .tex 文件（main.tex, introduction.tex, method.tex, experiments.tex, conclusion.tex, appendix_proofs.tex, related_work.tex 等），找出并修复斜体滥用。\n\n**合法斜体用途（保留）**：\n- 首次定义术语（仅第一次出现时）\n- 数学变量（应在 `$...$` 里，不是 `\\textit{}`）\n- 论文/书籍标题\n- 拉丁缩写（e.g., i.e., et al., vis-à-vis）\n- `\\emph{}` 用于真正需要强调的词（罕见）\n\n**需要修复的情况**：\n- `\\textit{}` / `\\emph{}` 用于不该强调的普通术语或描述\n- 同一个术语被反复斜体（应只在首次定义时斜体）\n- placeholder 式的斜体说明（如 \"in progress\"）\n- 数学变量用 `\\textit{}` 而非 `$...$`\n\n对每个发现的问题，用 Edit 工具修复。记录每处修改的位置和原因。\n\n### Part 2: 附录公式与正文重叠\n\n1. 先读 `docs/paper/method.tex` 和 `docs/paper/experiments.tex`，收集所有有 `\\label{eq:...}` 的公式及其内容\n2. 再读 `docs/paper/appendix_proofs.tex`（和其他附录文件如 `k3_symmetric_proof.tex`），找出与正文重复的公式\n\n**处理规则**：\n- **完全重复**（附录复制了正文公式）→ 删掉附录中的重复公式，改为 \"Recall Equation~\\ref{eq:xxx}\" 或 \"From Equation~\\ref{eq:xxx} in the main text\"\n- **小变形/展开**（附录在正文公式基础上做推导）→ 保留但加引用，如 \"Starting from Equation~\\ref{eq:xxx},\"\n- **附录独有**（正文没有的推导步骤）→ 保留不动\n\n### Part 3: 编译验证\n\n```bash\ncd /home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper && latexmk -pdf -interaction=nonstopmode main.tex 2>&1 | tail -20\n```\n\n确认：\n- 0 errors\n- 0 undefined references（grep \"undefined\" in .log）\n- 论文仍在 8 页以内\n\n### 输出\n汇报：\n1. 斜体修复清单（文件:行号, 修改内容, 原因）\n2. 公式重复清理清单（文件:行号, 处理方式）\n3. 编译结果"
}
````

---

### Runtime record

_source line 2 · 2026-05-24T06:35:20.036Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-24T06:35:20.036Z",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

## Round 1

109 recorded events

### User

_source line 3 · 2026-05-24T06:35:20.062Z_

&lt;project_context>
# 项目: causal_annot_error_attrib

## 运行环境
- 服务器名: home-1x5090
- SSH 账户: sonny（调用 ssh_execute / submit_training_job 时传入 account="sonny"）
- SSH 连接命令: ssh implicit5638.xyfu.me  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /home/sonny/causal_annot_error_attrib


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
## 任务：全文斜体滥用修复 + 附录公式重复清理

### 项目根目录
`/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/`

### Part 1: 斜体滥用修复

通读 `docs/paper/` 下所有 .tex 文件（main.tex, introduction.tex, method.tex, experiments.tex, conclusion.tex, appendix_proofs.tex, related_work.tex 等），找出并修复斜体滥用。

**合法斜体用途（保留）**：
- 首次定义术语（仅第一次出现时）
- 数学变量（应在 `$...$` 里，不是 `\textit{}`）
- 论文/书籍标题
- 拉丁缩写（e.g., i.e., et al., vis-à-vis）
- `\emph{}` 用于真正需要强调的词（罕见）

**需要修复的情况**：
- `\textit{}` / `\emph{}` 用于不该强调的普通术语或描述
- 同一个术语被反复斜体（应只在首次定义时斜体）
- placeholder 式的斜体说明（如 "in progress"）
- 数学变量用 `\textit{}` 而非 `$...$`

对每个发现的问题，用 Edit 工具修复。记录每处修改的位置和原因。

### Part 2: 附录公式与正文重叠

1. 先读 `docs/paper/method.tex` 和 `docs/paper/experiments.tex`，收集所有有 `\label{eq:...}` 的公式及其内容
2. 再读 `docs/paper/appendix_proofs.tex`（和其他附录文件如 `k3_symmetric_proof.tex`），找出与正文重复的公式

**处理规则**：
- **完全重复**（附录复制了正文公式）→ 删掉附录中的重复公式，改为 "Recall Equation~\ref{eq:xxx}" 或 "From Equation~\ref{eq:xxx} in the main text"
- **小变形/展开**（附录在正文公式基础上做推导）→ 保留但加引用，如 "Starting from Equation~\ref{eq:xxx},"
- **附录独有**（正文没有的推导步骤）→ 保留不动

### Part 3: 编译验证

```bash
cd /home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper && latexmk -pdf -interaction=nonstopmode main.tex 2>&1 | tail -20
```

确认：
- 0 errors
- 0 undefined references（grep "undefined" in .log）
- 论文仍在 8 页以内

### 输出
汇报：
1. 斜体修复清单（文件:行号, 修改内容, 原因）
2. 公式重复清理清单（文件:行号, 处理方式）
3. 编译结果

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "69e21490-5eed-4263-bd47-6b3337c91359",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-24T06:35:20.062Z_

```json
{
  "parentUuid": "69e21490-5eed-4263-bd47-6b3337c91359",
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
  "uuid": "c5ae33d1-fd81-4f57-baee-51e53b5d8bef",
  "timestamp": "2026-05-24T06:35:20.062Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-24T06:35:20.062Z_

```json
{
  "parentUuid": "c5ae33d1-fd81-4f57-baee-51e53b5d8bef",
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
  "uuid": "b5912430-198a-4915-a033-9e0d69fc7f2d",
  "timestamp": "2026-05-24T06:35:20.062Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 6 · 2026-05-24T06:35:20.062Z_

```json
{
  "parentUuid": "b5912430-198a-4915-a033-9e0d69fc7f2d",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "953ff62c-d0fe-410f-a9a7-94fe4ffa68b4",
  "timestamp": "2026-05-24T06:35:20.062Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
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
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 8 · 2026-05-24T06:35:25.759Z_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading all the .tex files to identify italic abuse and formula duplication issues.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "953ff62c-d0fe-410f-a9a7-94fe4ffa68b4",
  "isSidechain": false,
  "requestId": "req_011CbLvsc13xSh3DaHmJ8sFu",
  "type": "assistant",
  "uuid": "7f4f8cc2-191a-4c55-8e5a-1621e2e56c3c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019EgGbcz6tG8tt1qCt24dwu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13681,
      "cache_read_input_tokens": 11841,
      "output_tokens": 153,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13681,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 153,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13681,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13681
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-24T06:35:26.328Z_

I'll read all the .tex files in parallel to start both parts simultaneously.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7f4f8cc2-191a-4c55-8e5a-1621e2e56c3c",
  "isSidechain": false,
  "requestId": "req_011CbLvsc13xSh3DaHmJ8sFu",
  "type": "assistant",
  "uuid": "a5411e7a-0ae8-431e-b514-ce03d925d4c8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019EgGbcz6tG8tt1qCt24dwu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13681,
      "cache_read_input_tokens": 11841,
      "output_tokens": 153,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13681,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 153,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13681,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13681
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-24T06:35:26.990Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01U5FW2LBryujwDx3ZnJNmU9`</summary>

```json
{
  "pattern": "docs/paper/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a5411e7a-0ae8-431e-b514-ce03d925d4c8",
  "isSidechain": false,
  "requestId": "req_011CbLvsc13xSh3DaHmJ8sFu",
  "type": "assistant",
  "uuid": "29ed91bc-bd58-44fd-93a7-409193c4ba0c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019EgGbcz6tG8tt1qCt24dwu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13681,
      "cache_read_input_tokens": 11841,
      "output_tokens": 153,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13681,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 153,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13681,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13681
          },
          "type": "message"
        }
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

_source line 11 · 2026-05-24T06:35:27.051Z_

<details><summary>↩ Tool result · `toolu_01U5FW2LBryujwDx3ZnJNmU9`</summary>

```text
docs/paper/exp_a_stress_test_table.tex
docs/paper/exp_e_asv_stability_table.tex
docs/paper/main.tex
docs/paper/e2e_demo_table.tex
docs/paper/conjecture_dgp_sensitivity_table.tex
docs/paper/k3_symmetric_proof.tex
docs/paper/e2e_real_cm_table.tex
docs/paper/abstract.tex
docs/paper/related_work.tex
docs/paper/method.tex
docs/paper/experiments.tex
docs/paper/introduction.tex
docs/paper/conclusion.tex
docs/paper/appendix_proofs.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "29ed91bc-bd58-44fd-93a7-409193c4ba0c",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "695a091d-f63d-45a7-b11e-6a705224d465",
  "toolUseResult": {
    "filenames": [
      "docs/paper/exp_a_stress_test_table.tex",
      "docs/paper/exp_e_asv_stability_table.tex",
      "docs/paper/main.tex",
      "docs/paper/e2e_demo_table.tex",
      "docs/paper/conjecture_dgp_sensitivity_table.tex",
      "docs/paper/k3_symmetric_proof.tex",
      "docs/paper/e2e_real_cm_table.tex",
      "docs/paper/abstract.tex",
      "docs/paper/related_work.tex",
      "docs/paper/method.tex",
      "docs/paper/experiments.tex",
      "docs/paper/introduction.tex",
      "docs/paper/conclusion.tex",
      "docs/paper/appendix_proofs.tex"
    ],
    "durationMs": 54,
    "numFiles": 14,
    "truncated": false
  },
  "sourceToolAssistantUUID": "29ed91bc-bd58-44fd-93a7-409193c4ba0c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-24T06:35:29.464Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LgpKGMkL1AwFxf53uEsia4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "695a091d-f63d-45a7-b11e-6a705224d465",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "e0e7379a-ee8a-440d-9613-d9bc3d569921",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 13 · 2026-05-24T06:35:29.475Z_

<details><summary>↩ Tool result · `toolu_01LgpKGMkL1AwFxf53uEsia4`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Large language models are rapidly replacing human annotators in computational social science, with researchers using LLM-generated labels for tasks ranging from sentiment classification to political stance detection~\cite{gilardi2023chatgpt, ziems2024can, egami_hinck_stewart_wei2023, baumann2025}. Crucially, most of these tasks are inherently multi-class: stance detection uses 3--4 categories, sentiment analysis 5, and disaster response taxonomies 10 or more. This shift promises dramatic cost reduction, but introduces a critical validity gap: annotation errors (equivalently, misclassification) from imperfect classifiers propagate into downstream causal estimates in ways that depend on both the error structure and the causal design. \citet{baumann2025} demonstrate that across 37 annotation tasks, 31\% of hypotheses yield incorrect conclusions with state-of-the-art LLMs, rising to 50\% for smaller models; these errors are highly correlated across models (60\% agreement when both err)~\cite{kim_garg2025}, undermining ensemble-based mitigation. Analyzing the \emph{structure} of annotation error, rather than simply reducing its magnitude, is essential for valid downstream inference. Standard classification metrics do not capture this risk: within an $F_1$ range of 0.61--0.69 across three frontier LLMs, causal bias varies by an order of magnitude across topologies.
5	
6	The transition at $K{\geq}3$ is not gradual but structural. For $K{=}2$, the stochastic constraint forces any confusion matrix with positive diagonal to preserve coefficient signs---an algebraic property of the $2{\times}2$ matrix dimension~\cite{brenner1993}. This guarantee \emph{vanishes} at $K{\geq}3$: the higher-dimensional confusion matrix admits negative effective weights on categories with opposite-sign coefficients, enabling sign reversal even under high accuracy~\cite{veirod_laake2001}. Under a uniform Dirichlet prior, 83.4\% of $K{=}3$ exposure confusion matrices produce sign reversal of at least one secondary coefficient; under realistic accuracy (diagonal $\geq 0.7$), 2.1\% still do. The primary treatment coefficient is never reversed under the tested $\beta$ configurations where a single category dominates ($\beta_1 \gg \beta_2$)---an empirical regularity we discuss in Section~\ref{sec:method}.
7	
8	Concretely, $F_1$ shows no rank correlation with causal bias ($\rho = -0.10$, $p = 0.45$ across 56 HumAID scenarios; bias ranges from 4.1\% to 42.1\% within $F_1$ 0.614--0.690). This fundamental asymmetry has received limited systematic treatment. \citet{dosemeci1990} and \citet{veirod_laake2001} noted the possibility of polytomous sign reversal; \citet{brenner1993} identified amplification for polytomous confounders; \citet{lee_wood_doughty2024} extended classifier error analysis to categorical variables and LLM classifiers, but covered only one DAG topology. We present the first systematic analysis that jointly addresses multi-class ($K{\geq}3$) misclassification across multiple DAG topologies under structural equation models, extending prior binary or single-topology analyses~\cite{brenner1993, teblunthuis2024}. Our analytical predictions match Monte Carlo estimates within 1.6\% MAPE across 161 scenarios.
9	
10	We address these gaps with three contributions:
11	
12	\begin{enumerate}
13	\item \textbf{Multi-class bias taxonomy.} We derive bias expressions for seven canonical DAG topologies\footnote{These span the four structural roles of the annotated variable: treatment (exposure), outcome-side covariate (confounding, mediation, M-bias, front-door), selection variable (collider), and instrument (IV).} (Figure~\ref{fig:dag_taxonomy}) under $K$-class non-differential misclassification, establishing a sign-preservation/reversal dichotomy: five topologies preserve the treatment effect sign, while exposure and IV can reverse it (binarization amplifies this gap $>$150${\times}$, from $\bar{\Delta}{=}0.006$ for M-bias to $0.926$ for IV; Appendix~\ref{app:binarization}).
14	
15	\item \textbf{Annotation Sensitivity Values.} Building on the bias taxonomy, we define three ASV diagnostics---magnitude, significance, and sign-flip---with proved envelope monotonicity for $K{=}2$ (Theorem~\ref{thm:monotone}) and $K{=}3$ symmetric confusion matrices (Theorem~\ref{thm:k3_symmetric}), with $\varepsilon$-approximate monotonicity for general $K{\geq}3$ ($\varepsilon < 0.017$ across 545{,}945 adversarial curves spanning four structural families; Conjecture~\ref{conj:monotone}). These reveal a vulnerability spectrum from IV (maximally fragile) to M-bias (immune, ASV $= \infty$), enabling topology-specific error tolerance assessment.
16	
17	\item \textbf{Topology-aware correction routing.} We observe that FWL invariance renders matrix-based corrections provably ineffective under linear regression for four covariate topologies, and evaluate five methods across 210 configurations---PPI++ harms M-bias ($-88\%$), MC-SIMEX degrades front-door ($-62.4\%$)---and provide a topology-aware decision procedure (Algorithm~\ref{alg:correction}, Appendix), validated end-to-end with production LLM confusion matrices from VAST stance detection (Appendix~\ref{sec:real_cm_demo}).
18	\end{enumerate}
19	
20	Counterintuitively, applying corrections without topology awareness can \emph{worsen} estimates: PPI++ harms M-bias by 88\% and topology-agnostic IV correction amplifies bias by 139\%.
21	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e0e7379a-ee8a-440d-9613-d9bc3d569921",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "11d92804-173c-443a-a84f-fbf78066879e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nLarge language models are rapidly replacing human annotators in computational social science, with researchers using LLM-generated labels for tasks ranging from sentiment classification to political stance detection~\\cite{gilardi2023chatgpt, ziems2024can, egami_hinck_stewart_wei2023, baumann2025}. Crucially, most of these tasks are inherently multi-class: stance detection uses 3--4 categories, sentiment analysis 5, and disaster response taxonomies 10 or more. This shift promises dramatic cost reduction, but introduces a critical validity gap: annotation errors (equivalently, misclassification) from imperfect classifiers propagate into downstream causal estimates in ways that depend on both the error structure and the causal design. \\citet{baumann2025} demonstrate that across 37 annotation tasks, 31\\% of hypotheses yield incorrect conclusions with state-of-the-art LLMs, rising to 50\\% for smaller models; these errors are highly correlated across models (60\\% agreement when both err)~\\cite{kim_garg2025}, undermining ensemble-based mitigation. Analyzing the \\emph{structure} of annotation error, rather than simply reducing its magnitude, is essential for valid downstream inference. Standard classification metrics do not capture this risk: within an $F_1$ range of 0.61--0.69 across three frontier LLMs, causal bias varies by an order of magnitude across topologies.\n\nThe transition at $K{\\geq}3$ is not gradual but structural. For $K{=}2$, the stochastic constraint forces any confusion matrix with positive diagonal to preserve coefficient signs---an algebraic property of the $2{\\times}2$ matrix dimension~\\cite{brenner1993}. This guarantee \\emph{vanishes} at $K{\\geq}3$: the higher-dimensional confusion matrix admits negative effective weights on categories with opposite-sign coefficients, enabling sign reversal even under high accuracy~\\cite{veirod_laake2001}. Under a uniform Dirichlet prior, 83.4\\% of $K{=}3$ exposure confusion matrices produce sign reversal of at least one secondary coefficient; under realistic accuracy (diagonal $\\geq 0.7$), 2.1\\% still do. The primary treatment coefficient is never reversed under the tested $\\beta$ configurations where a single category dominates ($\\beta_1 \\gg \\beta_2$)---an empirical regularity we discuss in Section~\\ref{sec:method}.\n\nConcretely, $F_1$ shows no rank correlation with causal bias ($\\rho = -0.10$, $p = 0.45$ across 56 HumAID scenarios; bias ranges from 4.1\\% to 42.1\\% within $F_1$ 0.614--0.690). This fundamental asymmetry has received limited systematic treatment. \\citet{dosemeci1990} and \\citet{veirod_laake2001} noted the possibility of polytomous sign reversal; \\citet{brenner1993} identified amplification for polytomous confounders; \\citet{lee_wood_doughty2024} extended classifier error analysis to categorical variables and LLM classifiers, but covered only one DAG topology. We present the first systematic analysis that jointly addresses multi-class ($K{\\geq}3$) misclassification across multiple DAG topologies under structural equation models, extending prior binary or single-topology analyses~\\cite{brenner1993, teblunthuis2024}. Our analytical predictions match Monte Carlo estimates within 1.6\\% MAPE across 161 scenarios.\n\nWe address these gaps with three contributions:\n\n\\begin{enumerate}\n\\item \\textbf{Multi-class bias taxonomy.} We derive bias expressions for seven canonical DAG topologies\\footnote{These span the four structural roles of the annotated variable: treatment (exposure), outcome-side covariate (confounding, mediation, M-bias, front-door), selection variable (collider), and instrument (IV).} (Figure~\\ref{fig:dag_taxonomy}) under $K$-class non-differential misclassification, establishing a sign-preservation/reversal dichotomy: five topologies preserve the treatment effect sign, while exposure and IV can reverse it (binarization amplifies this gap $>$150${\\times}$, from $\\bar{\\Delta}{=}0.006$ for M-bias to $0.926$ for IV; Appendix~\\ref{app:binarization}).\n\n\\item \\textbf{Annotation Sensitivity Values.} Building on the bias taxonomy, we define three ASV diagnostics---magnitude, significance, and sign-flip---with proved envelope monotonicity for $K{=}2$ (Theorem~\\ref{thm:monotone}) and $K{=}3$ symmetric confusion matrices (Theorem~\\ref{thm:k3_symmetric}), with $\\varepsilon$-approximate monotonicity for general $K{\\geq}3$ ($\\varepsilon < 0.017$ across 545{,}945 adversarial curves spanning four structural families; Conjecture~\\ref{conj:monotone}). These reveal a vulnerability spectrum from IV (maximally fragile) to M-bias (immune, ASV $= \\infty$), enabling topology-specific error tolerance assessment.\n\n\\item \\textbf{Topology-aware correction routing.} We observe that FWL invariance renders matrix-based corrections provably ineffective under linear regression for four covariate topologies, and evaluate five methods across 210 configurations---PPI++ harms M-bias ($-88\\%$), MC-SIMEX degrades front-door ($-62.4\\%$)---and provide a topology-aware decision procedure (Algorithm~\\ref{alg:correction}, Appendix), validated end-to-end with production LLM confusion matrices from VAST stance detection (Appendix~\\ref{sec:real_cm_demo}).\n\\end{enumerate}\n\nCounterintuitively, applying corrections without topology awareness can \\emph{worsen} estimates: PPI++ harms M-bias by 88\\% and topology-agnostic IV correction amplifies bias by 139\\%.\n",
      "numLines": 21,
      "startLine": 1,
      "totalLines": 21
    }
  },
  "sourceToolAssistantUUID": "e0e7379a-ee8a-440d-9613-d9bc3d569921",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-24T06:35:29.798Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JLmeFkiph9kZTobjPn6uJ6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "11d92804-173c-443a-a84f-fbf78066879e",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "23f39202-bcd7-4d11-8c5c-91968c130168",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 15 · 2026-05-24T06:35:33.556Z_

<details><summary>↩ Tool result · `toolu_01Se1xLjRskY3vRa3aqCe1rS`</summary>

```text
1	% K=3 Symmetric Confusion Matrix: Monotonicity Proof
2	% Theorem statement is in method.tex; this file contains the proof and remarks only.
3	
4	\begin{proof}
5	All three parts reduce to a single lemma about the between-group variance
6	$V_B(\delta)=\operatorname{Var}\bigl(\mathbb{E}[g(A)\mid A^*_\delta]\bigr)$.
7	
8	\paragraph{Step 1: Structural reduction.}
9	The symmetric $C_0$ decomposes as $C_0=(1{-}3c)\,I+c\,\mathbf{1}\mathbf{1}^\top$, so
10	\[
11	  C(\delta) = (1{-}\delta)I + \delta\bigl[(1{-}3c)\,I+c\,\mathbf{1}\mathbf{1}^\top\bigr]
12	  = (1{-}3c\delta)\,I + c\delta\,\mathbf{1}\mathbf{1}^\top.
13	\]
14	Setting $s=c\delta\in[0,c]$, each entry is
15	$C(\delta)_{j\ell}=(1{-}3s)\,\mathbf{1}_{j=\ell}+s$,
16	so $C(\delta)$ stays in the one-parameter symmetric family.
17	In particular:
18	\begin{align}
19	  q_j(s) &= \textstyle\sum_k C(\delta)_{jk}\,p_k = (1{-}3s)\,p_j + s, \label{eq:k3q} \\
20	  \mu_j(s) &\equiv \mathbb{E}[g(A)\mid A^*{=}j]
21	  = \bar{g} + \frac{(1{-}3s)\,p_j\,h_j}{q_j(s)}, \label{eq:k3mu}
22	\end{align}
23	where $h_j=g_j-\bar{g}$, $\bar{g}=\sum_k p_k g_k$.
24	
25	\paragraph{Step 2: Closed-form $V_B(s)$.}
26	The between-group variance admits a clean factorization:
27	\begin{equation}
28	  V_B(s) = \sum_j q_j\,(\mu_j-\bar{g})^2
29	  = (1{-}3s)^2\sum_{j=0}^{2}\frac{p_j^2\,h_j^2}{q_j(s)}.
30	  \label{eq:k3VB}
31	\end{equation}
32	\emph{Verification.}
33	At $s{=}0$: $q_j{=}p_j$, so $V_B(0)=\sum_j p_j h_j^2=\operatorname{Var}(g)$.
34	At $s{=}\tfrac{1}{3}$: $V_B(\tfrac{1}{3})=0$.
35	
36	\paragraph{Step 3: $V_B$ is strictly decreasing on $[0,\tfrac{1}{3})$ (pointwise, not just at endpoints).}
37	Differentiating~\eqref{eq:k3VB} via the product rule:
38	\begin{equation}
39	  \frac{dV_B}{ds}
40	  = (1{-}3s)\sum_{j=0}^{2}\frac{p_j^2\,h_j^2}{q_j^2}\;\bigl[\underbrace{-3(1{-}3s)\,p_j - 1 - 3s}_{\displaystyle\Lambda_j(s)}\bigr].
41	  \label{eq:k3dVB}
42	\end{equation}
43	
44	\emph{Derivation.}
45	Write $V_B=(1{-}3s)^2 F(s)$ with $F(s)=\sum_j p_j^2 h_j^2/q_j(s)$.
46	The product rule gives $V_B'=-6(1{-}3s)F+(1{-}3s)^2 F'$.
47	Since $q_j'(s)=1{-}3p_j$, we have $F'(s)=\sum_j p_j^2 h_j^2(3p_j{-}1)/q_j^2$.
48	Combining:
49	\begin{align*}
50	  V_B'
51	  &= (1{-}3s)\Bigl[-6\sum_j \frac{p_j^2 h_j^2}{q_j}+(1{-}3s)\sum_j \frac{p_j^2 h_j^2(3p_j{-}1)}{q_j^2}\Bigr] \\
52	  &= (1{-}3s)\sum_j \frac{p_j^2 h_j^2}{q_j^2}\bigl[-6q_j+(1{-}3s)(3p_j{-}1)\bigr].
53	\end{align*}
54	Expanding the bracket:
55	\[
56	  -6q_j+(1{-}3s)(3p_j{-}1)
57	  = -6(1{-}3s)p_j-6s+3(1{-}3s)p_j-(1{-}3s)
58	  = -3(1{-}3s)p_j-1-3s
59	  = \Lambda_j(s).
60	\]
61	
62	\emph{Sign analysis.}
63	For $s\in[0,\tfrac{1}{3})$: $(1{-}3s)>0$, $p_j\geq 0$, so
64	\[
65	  \Lambda_j(s) = -3(1{-}3s)\,p_j - (1+3s) < 0
66	  \quad\text{for all } j,
67	\]
68	since $1+3s>0$ alone forces $\Lambda_j<0$.
69	Every term $p_j^2 h_j^2/q_j^2\geq 0$, and the prefactor $(1{-}3s)>0$.
70	Hence $dV_B/ds\leq 0$ for all $s\in[0,\tfrac{1}{3})$.
71	
72	\emph{Strict inequality.}
73	If $\operatorname{Var}(g){>}0$, at least two categories $j$ satisfy $p_j>0$ and $h_j\neq 0$, contributing strictly positive terms.
74	Since $\Lambda_j<0$, the sum is strictly negative:
75	$dV_B/ds<0$ for all $s\in(0,\tfrac{1}{3})$.
76	
77	\paragraph{Step 4: From $V_B$ to $|B|$ --- confounding (a).}
78	Under proportional effects $f=\lambda g$ (Proposition~\ref{prop:conf_prop}):
79	\[
80	  B(C(\delta)) = \frac{\lambda\,V_W(\delta)}{V_W(\delta)+\sigma_T^2},
81	  \quad V_W(\delta)=\operatorname{Var}(g)-V_B(c\delta).
82	\]
83	Step~3 shows $V_B(s)$ is strictly decreasing in $s=c\delta$, so $V_W(\delta)$ is strictly increasing from $0$ to $\operatorname{Var}(g)$.
84	Since $x\mapsto |\lambda|\,x/(x+\sigma_T^2)$ is strictly increasing for $x\geq 0$:
85	\[
86	  |B(C(\delta))| = |\lambda|\,\frac{V_W(\delta)}{V_W(\delta)+\sigma_T^2}
87	\]
88	is strictly non-decreasing.
89	
90	\paragraph{Step 5: Mediation (b).}
91	Under proportional effects $f=\lambda g$ with $g(k)=\mathbb{E}[T\mid A{=}k]$, the mediation bias
92	(§\ref{par:med_monotone}) has the identical form
93	$B=\lambda\,V_W/(V_W+\sigma_\varepsilon^2)$
94	with $\sigma_\varepsilon^2=\mathbb{E}[\operatorname{Var}(T\mid A)]$ replacing $\sigma_T^2$.
95	The same argument yields $|B|$ strictly non-decreasing.
96	
97	\paragraph{Step 6: Collider (c).}
98	Under proportional effects $h=\lambda g$ (Proposition~\ref{prop:col_prop}):
99	\[
100	  B_{\mathrm{col}}(C(\delta)) = -\frac{\lambda\,V_B(c\delta)}{\operatorname{Var}(T)-V_B(c\delta)},
101	  \qquad
102	  |B_{\mathrm{col}}| = |\lambda|\,\frac{V_B(c\delta)}{\operatorname{Var}(T)-V_B(c\delta)}.
103	\]
104	Since $x\mapsto x/(a{-}x)$ is strictly increasing for $x\in[0,a)$
105	and $V_B(s)$ is strictly decreasing (Step~3),
106	$|B_{\mathrm{col}}(C(\delta))|$ is strictly non-increasing:
107	from $|B_{\mathrm{Berkson}}|=|\lambda|\,V_g/(\operatorname{Var}(T){-}V_g)$ at $\delta{=}0$
108	to $0$ at $\delta$ such that $V_B\to 0$.
109	\end{proof}
110	
111	\begin{remark}[Comparison with the general-$K$ proof]
112	\label{rem:k3_vs_general}
113	The general-$K$ monotonicity proof (§\ref{app:monotonicity_proof}) relies on
114	convexity of $V_B(\delta)$ plus the endpoint condition $V_B'(1)\leq 0$,
115	the latter verified only for $K{=}2$ analytically and $K\geq 3$ numerically.
116	The $K{=}3$ symmetric proof is \emph{stronger}:
117	it establishes $dV_B/ds<0$ at every interior point via the signed decomposition~\eqref{eq:k3dVB},
118	bypassing both the convexity argument and the endpoint condition entirely.
119	The key enabler is that the symmetric $C_0$ keeps $C(\delta)$ within the one-parameter family
120	$(1{-}3s)I+s\,\mathbf{1}\mathbf{1}^\top$, yielding the factored form~\eqref{eq:k3VB}
121	in which the $(1{-}3s)^2$ prefactor and the $q_j^{-1}$ terms interact to produce
122	a uniformly signed derivative.
123	\end{remark}
124	
125	\begin{remark}[General (non-proportional) effects]
126	\label{rem:k3_general}
127	For non-proportional effects ($f\neq\lambda g$), the confounding bias
128	$B(C)=\mathbb{E}[\operatorname{Cov}(g,f\mid A^*)]/D(C)$
129	does not factor through $V_W$ alone,
130	and exact monotonicity of $|B(C(\delta))|$ can fail even for $K{=}3$ symmetric $C_0$.
131	Numerical verification ($50{,}000$ random configurations) finds violations in ${\sim}10\%$ of cases,
132	with maximum step deviation ${\sim}0.004$,
133	confirming $\varepsilon$-approximate monotonicity consistent with the general-$K$ results
134	(Table~\ref{tab:conjecture_verify}).
135	\end{remark}
136	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8296c678-91f8-4b1f-b72c-6d1c8ce8b27f",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "93881f95-9c40-4e3e-b89b-02cbb8110d48",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/k3_symmetric_proof.tex",
      "content": "% K=3 Symmetric Confusion Matrix: Monotonicity Proof\n% Theorem statement is in method.tex; this file contains the proof and remarks only.\n\n\\begin{proof}\nAll three parts reduce to a single lemma about the between-group variance\n$V_B(\\delta)=\\operatorname{Var}\\bigl(\\mathbb{E}[g(A)\\mid A^*_\\delta]\\bigr)$.\n\n\\paragraph{Step 1: Structural reduction.}\nThe symmetric $C_0$ decomposes as $C_0=(1{-}3c)\\,I+c\\,\\mathbf{1}\\mathbf{1}^\\top$, so\n\\[\n  C(\\delta) = (1{-}\\delta)I + \\delta\\bigl[(1{-}3c)\\,I+c\\,\\mathbf{1}\\mathbf{1}^\\top\\bigr]\n  = (1{-}3c\\delta)\\,I + c\\delta\\,\\mathbf{1}\\mathbf{1}^\\top.\n\\]\nSetting $s=c\\delta\\in[0,c]$, each entry is\n$C(\\delta)_{j\\ell}=(1{-}3s)\\,\\mathbf{1}_{j=\\ell}+s$,\nso $C(\\delta)$ stays in the one-parameter symmetric family.\nIn particular:\n\\begin{align}\n  q_j(s) &= \\textstyle\\sum_k C(\\delta)_{jk}\\,p_k = (1{-}3s)\\,p_j + s, \\label{eq:k3q} \\\\\n  \\mu_j(s) &\\equiv \\mathbb{E}[g(A)\\mid A^*{=}j]\n  = \\bar{g} + \\frac{(1{-}3s)\\,p_j\\,h_j}{q_j(s)}, \\label{eq:k3mu}\n\\end{align}\nwhere $h_j=g_j-\\bar{g}$, $\\bar{g}=\\sum_k p_k g_k$.\n\n\\paragraph{Step 2: Closed-form $V_B(s)$.}\nThe between-group variance admits a clean factorization:\n\\begin{equation}\n  V_B(s) = \\sum_j q_j\\,(\\mu_j-\\bar{g})^2\n  = (1{-}3s)^2\\sum_{j=0}^{2}\\frac{p_j^2\\,h_j^2}{q_j(s)}.\n  \\label{eq:k3VB}\n\\end{equation}\n\\emph{Verification.}\nAt $s{=}0$: $q_j{=}p_j$, so $V_B(0)=\\sum_j p_j h_j^2=\\operatorname{Var}(g)$.\nAt $s{=}\\tfrac{1}{3}$: $V_B(\\tfrac{1}{3})=0$.\n\n\\paragraph{Step 3: $V_B$ is strictly decreasing on $[0,\\tfrac{1}{3})$ (pointwise, not just at endpoints).}\nDifferentiating~\\eqref{eq:k3VB} via the product rule:\n\\begin{equation}\n  \\frac{dV_B}{ds}\n  = (1{-}3s)\\sum_{j=0}^{2}\\frac{p_j^2\\,h_j^2}{q_j^2}\\;\\bigl[\\underbrace{-3(1{-}3s)\\,p_j - 1 - 3s}_{\\displaystyle\\Lambda_j(s)}\\bigr].\n  \\label{eq:k3dVB}\n\\end{equation}\n\n\\emph{Derivation.}\nWrite $V_B=(1{-}3s)^2 F(s)$ with $F(s)=\\sum_j p_j^2 h_j^2/q_j(s)$.\nThe product rule gives $V_B'=-6(1{-}3s)F+(1{-}3s)^2 F'$.\nSince $q_j'(s)=1{-}3p_j$, we have $F'(s)=\\sum_j p_j^2 h_j^2(3p_j{-}1)/q_j^2$.\nCombining:\n\\begin{align*}\n  V_B'\n  &= (1{-}3s)\\Bigl[-6\\sum_j \\frac{p_j^2 h_j^2}{q_j}+(1{-}3s)\\sum_j \\frac{p_j^2 h_j^2(3p_j{-}1)}{q_j^2}\\Bigr] \\\\\n  &= (1{-}3s)\\sum_j \\frac{p_j^2 h_j^2}{q_j^2}\\bigl[-6q_j+(1{-}3s)(3p_j{-}1)\\bigr].\n\\end{align*}\nExpanding the bracket:\n\\[\n  -6q_j+(1{-}3s)(3p_j{-}1)\n  = -6(1{-}3s)p_j-6s+3(1{-}3s)p_j-(1{-}3s)\n  = -3(1{-}3s)p_j-1-3s\n  = \\Lambda_j(s).\n\\]\n\n\\emph{Sign analysis.}\nFor $s\\in[0,\\tfrac{1}{3})$: $(1{-}3s)>0$, $p_j\\geq 0$, so\n\\[\n  \\Lambda_j(s) = -3(1{-}3s)\\,p_j - (1+3s) < 0\n  \\quad\\text{for all } j,\n\\]\nsince $1+3s>0$ alone forces $\\Lambda_j<0$.\nEvery term $p_j^2 h_j^2/q_j^2\\geq 0$, and the prefactor $(1{-}3s)>0$.\nHence $dV_B/ds\\leq 0$ for all $s\\in[0,\\tfrac{1}{3})$.\n\n\\emph{Strict inequality.}\nIf $\\operatorname{Var}(g){>}0$, at least two categories $j$ satisfy $p_j>0$ and $h_j\\neq 0$, contributing strictly positive terms.\nSince $\\Lambda_j<0$, the sum is strictly negative:\n$dV_B/ds<0$ for all $s\\in(0,\\tfrac{1}{3})$.\n\n\\paragraph{Step 4: From $V_B$ to $|B|$ --- confounding (a).}\nUnder proportional effects $f=\\lambda g$ (Proposition~\\ref{prop:conf_prop}):\n\\[\n  B(C(\\delta)) = \\frac{\\lambda\\,V_W(\\delta)}{V_W(\\delta)+\\sigma_T^2},\n  \\quad V_W(\\delta)=\\operatorname{Var}(g)-V_B(c\\delta).\n\\]\nStep~3 shows $V_B(s)$ is strictly decreasing in $s=c\\delta$, so $V_W(\\delta)$ is strictly increasing from $0$ to $\\operatorname{Var}(g)$.\nSince $x\\mapsto |\\lambda|\\,x/(x+\\sigma_T^2)$ is strictly increasing for $x\\geq 0$:\n\\[\n  |B(C(\\delta))| = |\\lambda|\\,\\frac{V_W(\\delta)}{V_W(\\delta)+\\sigma_T^2}\n\\]\nis strictly non-decreasing.\n\n\\paragraph{Step 5: Mediation (b).}\nUnder proportional effects $f=\\lambda g$ with $g(k)=\\mathbb{E}[T\\mid A{=}k]$, the mediation bias\n(§\\ref{par:med_monotone}) has the identical form\n$B=\\lambda\\,V_W/(V_W+\\sigma_\\varepsilon^2)$\nwith $\\sigma_\\varepsilon^2=\\mathbb{E}[\\operatorname{Var}(T\\mid A)]$ replacing $\\sigma_T^2$.\nThe same argument yields $|B|$ strictly non-decreasing.\n\n\\paragraph{Step 6: Collider (c).}\nUnder proportional effects $h=\\lambda g$ (Proposition~\\ref{prop:col_prop}):\n\\[\n  B_{\\mathrm{col}}(C(\\delta)) = -\\frac{\\lambda\\,V_B(c\\delta)}{\\operatorname{Var}(T)-V_B(c\\delta)},\n  \\qquad\n  |B_{\\mathrm{col}}| = |\\lambda|\\,\\frac{V_B(c\\delta)}{\\operatorname{Var}(T)-V_B(c\\delta)}.\n\\]\nSince $x\\mapsto x/(a{-}x)$ is strictly increasing for $x\\in[0,a)$\nand $V_B(s)$ is strictly decreasing (Step~3),\n$|B_{\\mathrm{col}}(C(\\delta))|$ is strictly non-increasing:\nfrom $|B_{\\mathrm{Berkson}}|=|\\lambda|\\,V_g/(\\operatorname{Var}(T){-}V_g)$ at $\\delta{=}0$\nto $0$ at $\\delta$ such that $V_B\\to 0$.\n\\end{proof}\n\n\\begin{remark}[Comparison with the general-$K$ proof]\n\\label{rem:k3_vs_general}\nThe general-$K$ monotonicity proof (§\\ref{app:monotonicity_proof}) relies on\nconvexity of $V_B(\\delta)$ plus the endpoint condition $V_B'(1)\\leq 0$,\nthe latter verified only for $K{=}2$ analytically and $K\\geq 3$ numerically.\nThe $K{=}3$ symmetric proof is \\emph{stronger}:\nit establishes $dV_B/ds<0$ at every interior point via the signed decomposition~\\eqref{eq:k3dVB},\nbypassing both the convexity argument and the endpoint condition entirely.\nThe key enabler is that the symmetric $C_0$ keeps $C(\\delta)$ within the one-parameter family\n$(1{-}3s)I+s\\,\\mathbf{1}\\mathbf{1}^\\top$, yielding the factored form~\\eqref{eq:k3VB}\nin which the $(1{-}3s)^2$ prefactor and the $q_j^{-1}$ terms interact to produce\na uniformly signed derivative.\n\\end{remark}\n\n\\begin{remark}[General (non-proportional) effects]\n\\label{rem:k3_general}\nFor non-proportional effects ($f\\neq\\lambda g$), the confounding bias\n$B(C)=\\mathbb{E}[\\operatorname{Cov}(g,f\\mid A^*)]/D(C)$\ndoes not factor through $V_W$ alone,\nand exact monotonicity of $|B(C(\\delta))|$ can fail even for $K{=}3$ symmetric $C_0$.\nNumerical verification ($50{,}000$ random configurations) finds violations in ${\\sim}10\\%$ of cases,\nwith maximum step deviation ${\\sim}0.004$,\nconfirming $\\varepsilon$-approximate monotonicity consistent with the general-$K$ results\n(Table~\\ref{tab:conjecture_verify}).\n\\end{remark}\n",
      "numLines": 136,
      "startLine": 1,
      "totalLines": 136
    }
  },
  "sourceToolAssistantUUID": "8296c678-91f8-4b1f-b72c-6d1c8ce8b27f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-24T06:35:29.809Z_

<details><summary>↩ Tool result · `toolu_01JLmeFkiph9kZTobjPn6uJ6`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Setup and Notation}
5	\label{sec:notation}
6	
7	Let $A$ denote a true $K$-class categorical variable (e.g., sentiment with $K{=}3$ levels) and $A^*$ its observed, potentially misclassified version produced by an LLM annotator. The misclassification process is characterized by a $K{\times}K$ confusion matrix $C$ with entries $C_{jk} = P(A^*{=}j \mid A{=}k)$, where each column sums to one (column-stochastic: each column gives the distribution of predicted labels for a given true label). Following \citet{hernan_cole2009}, we represent this measurement process using \emph{starred-node} DAGs: the true variable $A$ is latent, and the observed $A^*$ is connected to $A$ via a dashed measurement edge.
8	
9	\paragraph{Notation conventions.}
10	Our analysis characterizes probability limits (plim, $N \to \infty$) rather than finite-sample variance. The FWL theorem~\cite{frisch1933partial} guarantees that each regression coefficient equals the coefficient from a simple regression after residualizing all other variables---this is why matrix-based corrections fail for covariate topologies (Section~\ref{sec:correction}). Table~\ref{tab:notation} (Appendix~\ref{app:notation_table}) collects all notation.
11	
12	\begin{definition}[Non-differential misclassification]
13	\label{def:nondiff}
14	Misclassification of $A$ is non-differential with respect to outcome $Y$ and covariates $\mathbf{Z}$ if $P(A^*{=}j \mid A{=}k, Y, \mathbf{Z}) = P(A^*{=}j \mid A{=}k) = C_{jk}$ for all $j,k$.
15	\end{definition}
16	
17	In batch annotation pipelines, the LLM processes each text independently without access to $Y$, making non-differentiality an architectural invariant~\cite{ziems2024can}; Y-stratified permutation tests confirm this (1/12 rejection at $\alpha{=}0.05$; Appendix~\ref{sec:y_stratified_test}). Non-differentiality holds architecturally when $Y$ is external to the annotated text (e.g., health outcomes, voting behavior), since the LLM cannot condition on unobserved $Y$; it may be violated when $Y$ correlates with text content (e.g., topic), in which case the Y-stratified test (Appendix~\ref{sec:y_stratified_test}) provides empirical verification. Under stress testing, sign reversal occurs in 14/16 $K{\geq}3$ exposure configurations at $\varepsilon{=}0.01$ structured departure, with sign-flip rate increasing from 2.0\% to 9.67\% at $\varepsilon{=}0.20$ (Appendix~\ref{sec:nondiff_stress}); formal degradation guarantees under differential misclassification remain an open problem.
18	
19	Throughout, $\tau$ denotes the causal estimand of interest, whose definition varies by topology: the confounder's coefficient, the treatment effect, the indirect effect, or the Wald ratio (Appendix~\ref{app:confounding}ff.).
20	
21	We study seven canonical DAG topologies (Figure~\ref{fig:dag_taxonomy})~\cite{pearl2009, hernan2020causal} in which $A$ occupies structurally distinct causal roles: confounder, exposure, mediator, collider, M-bias variable, front-door mediator, and instrument. Throughout, we derive probability limits under \emph{linear} structural equation models~\cite{carroll2006}, the standard framework for exact characterization of topology-dependent bias; robustness under logistic regression~\cite{stefanski_carroll1985} is verified in Appendix~\ref{sec:logistic_dgp} and~\ref{sec:fwl_nonlinear}.
22	
23	\subsection{Multi-Class Bias Expressions}
24	\label{sec:bias_expressions}
25	
26	For each topology, we derive the $\text{plim}$\footnote{The probability limit (plim) is the value to which an estimator converges as sample size $N \to \infty$; it characterizes systematic bias separately from sampling variability.} of the naive estimator that substitutes $A^*$ for $A$. Let $\tau$ denote the target causal parameter---its precise definition is topology-specific (e.g., the coefficient on $X$ for confounding, the category-specific $\beta_j$ for exposure, or the direct effect $\tau_{\text{direct}}$ for mediation)---and $\hat{\tau}(A^*)$ the estimator using misclassified annotations.
27	
28	\paragraph{Confounding ($A$ = confounder).}
29	When $A$ confounds the $X{\to}Y$ relationship, the OLS estimator controlling for $A^*$ has probability limit
30	\begin{equation}
31	\label{eq:confounding}
32	\text{plim}\;\hat{\tau}(A^*) = \bigl(\mathbb{E}[Z^{\prime}Z]\bigr)^{-1}\mathbb{E}[Z^{\prime}X]\,\boldsymbol{\beta},
33	\end{equation}
34	where $Z = [X, \text{dummies}(A^*)]$, $\boldsymbol{\beta}$ contains the true coefficients, and the target parameter $\tau$ is the coefficient on $X$. Misclassification produces residual confounding that monotonically approaches the omitted variable bias, but the sign of $\hat{\tau}$ is preserved: $\tau_{\text{sign\_flip}} = 0$ structurally.\footnote{Consistent with \citet{brenner1993}: misclassification degrades confounding control, producing amplification ($|\hat{\tau}| > |\tau|$, universal in this topology) but never sign reversal ($\text{sign}(\hat{\tau}) \neq \text{sign}(\tau)$).}
35	
36	\paragraph{Exposure ($A$ = treatment variable).}
37	When $A$ is the exposure of interest, the biased coefficient for category $j$ becomes a weighted combination of true coefficients:
38	\begin{equation}
39	\label{eq:exposure}
40	\text{plim}\;\hat{\beta}_j(A^*) = \sum_{k=1}^{K} w_{jk}\,\beta_k,
41	\end{equation}
42	where $w_{jk}$ depends on the confusion matrix $C$ and the population marginal $\pi_k = P(A{=}k)$. Unlike the binary case, where non-differential misclassification guarantees attenuation toward the null~\cite{brenner1993}, the $K{\geq}3$ case permits $w_{jk}$ to assign negative weight to categories with opposite-sign coefficients, producing \emph{sign reversal}. A near-permutation confusion matrix effectively swaps category labels, making sign reversal the dominant outcome (83.4\% under uniform Dirichlet prior). This failure mode is structurally impossible at $K{=}2$ because a $2{\times}2$ stochastic matrix with positive diagonal cannot reverse the sign of a single coefficient.
43	
44	\begin{figure*}[t]
45	\centering
46	\includegraphics[width=0.92\textwidth,height=0.18\textheight,keepaspectratio]{fig2_bias_distribution.pdf}
47	\vspace{-6pt}
48	\caption{Bias distributions under 100{,}000 random $K{=}3$ confusion matrices (uniform Dirichlet; realistic-accuracy results in Section~\ref{sec:taxonomy_results}). Red = sign reversal. Exposure: 83.4\% sign reversal; IV: 52.6\%.}
49	\label{fig:bias_distribution}
50	\end{figure*}
51	
52	\paragraph{Numerical Verification 2: Primary coefficient preservation.}
53	Across 23 empirical LLM configurations, the primary coefficient (the category with the largest true effect $|\beta_k|$) never reverses sign, while 61\% reverse a secondary (non-dominant) coefficient---confirmed under 100{,}000 Dirichlet matrices with diagonal ${\geq}\,0.7$ across six beta-ratio conditions (1.0 to 50.0) with 0\% primary sign-flip (Appendix~\ref{app:exposure}).
54	
55	\paragraph{Mediation ($A$ = mediator).}
56	When $A$ mediates the $X{\to}Y$ relationship~\cite{vanderweele2015explanation}, the direct effect estimator controlling for $A^*$ has probability limit
57	\begin{equation}
58	\label{eq:mediation}
59	\text{plim}\;\hat{\tau}_{\text{direct}}(A^*) = \tau_{\text{direct}} + \bigl(1 - \lambda(C)\bigr)\,\tau_{\text{indirect}},
60	\end{equation}
61	where $\lambda(C) \in [0,1]$ under proportional effects (Appendix~\ref{app:proof}, Proposition~\ref{prop:lambda_bound}), with $\lambda(I) = 1$ under perfect classification. Misclassification ($\lambda < 1$) causes the residual indirect effect to be absorbed into the direct path estimate, producing upward bias in $|\hat{\tau}_{\text{direct}}|$ but preserving the sign ($\tau_{\text{sign\_flip}} = 0$).
62	
63	\paragraph{Collider, M-bias, and front-door.}
64	Three topologies exhibit \emph{protective} or \emph{immune} behavior. \textbf{Collider:} conditioning on $A^*$ instead of $A$ attenuates the spurious path, so annotation error reduces collider bias ($\tau_{\text{sign\_flip}} = 0$). \textbf{M-bias:} in the M-shaped DAG~\cite{greenland2003}, misclassifying $A$ weakens the M-bias path; this topology is immune ($\text{ASV} = \infty$). \textbf{Front-door:} the front-door estimator~\cite{bellemare_bloem2024} is attenuated in both $X \to A$ and $A \to Y$ stages, producing moderate bias with $\tau_{\text{sign\_flip}} = 0$.
65	
66	\paragraph{Instrumental variable ($A$ = instrument).}
67	The Wald estimator~\cite{angrist_imbens1995} $\hat{\tau}_{\text{IV}} = \hat{\text{cov}}(A^*, Y) / \hat{\text{cov}}(A^*, X)$ has $C$ in the denominator. Misclassification can drive first-stage coefficients toward zero or reverse their sign; under random Dirichlet matrices, 52.6\% produce sign reversal, making IV the most fragile topology (Appendix~\ref{sec:iv_dirichlet_subspace}).
68	
69	\paragraph{Structural sign-flip guarantee.}
70	\begin{proposition}[Sign preservation---analytic results]
71	\label{prop:signflip}
72	Under non-differential misclassification with $C_{kk} > 0$ for all $k$:
73	\emph{(a)}~Confounding preserves sign when $\operatorname{sign}(\tau) = \operatorname{sign}(\tau {+} B_{\mathrm{OV}})$, where $B_{\mathrm{OV}} {=} \operatorname{Cov}(g(A),f(A))/\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\ref{app:confounding}).
74	\emph{(b)}~Collider preserves sign when $|\tau| > \sqrt{\operatorname{Var}(g)\operatorname{Var}(h)}/\mathbb{E}[\operatorname{Var}(T{\mid}A)]$ (Berkson attenuation; Appendix~\ref{app:collider}); empirically verified across 100{,}000 matrices with zero violations.
75	\emph{(c)}~Exposure can produce sign reversal for $K {\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\ref{app:exposure}).
76	\end{proposition}
77	
78	Sign preservation for non-exposure topologies holds under topology-specific conditions (Table~\ref{tab:sign_conditions}, Appendix~\ref{app:conditions}), verified across 100{,}000 random matrices with zero violations; analytic proofs for general $K$ remain open.
79	
80	\subsection{Annotation Sensitivity Values}
81	\label{sec:asv}
82	
83	We adapt the sensitivity analysis paradigm---E-values~\cite{vanderweele_ding2017}, partial-$R^2$ bounds~\cite{cinelli2020making}, coefficient stability~\cite{oster2019}---to $K{\times}K$ annotation error, defining Annotation Sensitivity Values (ASVs): we prove $\varepsilon$-approximate monotonicity along $C(\delta)$ (Theorem~\ref{thm:monotone}), reducing $K^2$ dimensions to a scalar; define three ASV diagnostics for topology-dependent failure modes; and combine ASVs with FWL invariance to route corrections.
84	
85	\paragraph{Parameterization.}
86	We set $C(\delta) = (1{-}\delta)I + \delta C_0$, where $C_0$ is a reference confusion matrix and $\delta \in [0,1]$ controls severity ($\delta{=}0$: perfect; $\delta{=}1$: matches $C_0$). This linear path is one of many in the column-stochastic polytope from $I$ to $C_0$; ASV thresholds are path-dependent, but our bootstrap procedure (Section~\ref{sec:asv_results}) captures estimation uncertainty along the empirical path. We recommend bootstrapping $C_0$ and reporting ASV confidence intervals (Appendix~\ref{sec:bootstrap_asv}).
87	\paragraph{Three ASV types.}
88	We define three complementary measures: (1)~\textbf{Magnitude ASV} $\delta^*_{\text{mag}} = \min\{\delta : |\text{plim}\;\hat{\tau}(C(\delta)) - \tau| > \epsilon\}$---analogous to E-values; (2)~\textbf{Significance ASV} $\delta^*_{\text{sig}} = \min\{\delta : |\text{plim}\;\hat{\tau}(C(\delta))| < z_{\alpha/2} \cdot SE(N)\}$---relevant for attenuating topologies; (3)~\textbf{Sign-flip ASV} $\delta^*_{\text{sf}} = \min\{\delta : \text{sign}(\hat{\tau}) \neq \text{sign}(\tau)\}$---exposure and IV only. The significance ASV depends on $N$ through $SE(N)$, exhibiting a sharp phase transition at a critical $N^*$ below which all rejections are blocked.
89	
90	\begin{theorem}[Envelope monotonicity---$K{=}2$]
91	\label{thm:monotone}
92	For $K{=}2$ confounding and mediation topologies with proportional effects ($f = \lambda g$ for some scalar $\lambda$) under $C(\delta) = (1{-}\delta)I + \delta C_0$ with $(C_0)_{jj} \geq \tfrac{1}{2}$, $|B(C(\delta))|$ is monotonically non-decreasing in $\delta \in [0,1]$.
93	\end{theorem}
94	
95	The proof (Appendix~\ref{app:monotonicity_proof},~\ref{par:med_monotone}) exploits perspective function convexity; $(C_0)_{jj}{\geq}\tfrac{1}{2}$ excludes degenerate matrices. Proportional effects ($f{=}\lambda g$) is plausible when overall annotation competence drives both paths (e.g., a single quality dimension); it may fail under multi-dimensional asymmetric confusion where different error modes affect $f$ and $g$ differentially. All 23 empirical configurations preserve sign under this assumption, with 97.3\% preserving sign under non-proportional effects (Appendix~\ref{sec:proportional_effects}; Tables~\ref{tab:proportional_effects},~\ref{tab:proportional_empirical}).
96	
97	\begin{theorem}[$K{=}3$ symmetric monotonicity]
98	\label{thm:k3_symmetric}
99	For $K{=}3$ with symmetric confusion matrix $C_{jk} = c$ for $j \neq k$ and $C_{kk} = 1{-}2c$, $c \in (0, 1/3)$, and proportional effects ($f{=}\lambda g$), envelope monotonicity holds exactly: $|B(C(\delta))|$ is strictly monotone in $\delta$ for confounding, mediation, and collider topologies whenever $\mathrm{Var}(g) > 0$.
100	\end{theorem}
101	
102	Theorem~\ref{thm:k3_symmetric} serves as a theoretical anchor: exact monotonicity is achievable at $K{=}3$ under symmetric $C_0$. For general asymmetric matrices (empirical $K{=}3$ median $d_{\mathrm{rel}}{=}0.33$; Remark~\ref{rem:symmetry}), Conjecture~\ref{conj:monotone} provides numerical coverage ($\varepsilon < 0.017$). The proof (Appendix~\ref{app:k3_symmetric_proof}) exploits the one-parameter reduction $s = c\delta$ to show $dV_B/ds < 0$ pointwise; under non-proportional effects, approximate monotonicity holds ($\varepsilon < 0.005$; Appendix~\ref{app:k3_symmetric_proof}, Remark~2).
103	
104	\paragraph{From proofs to numerical evidence.}
105	Theorems~\ref{thm:monotone}--\ref{thm:k3_symmetric} establish exact monotonicity for $K{=}2$ and $K{=}3$ symmetric matrices. The factorization in Appendix~\ref{app:k3_symmetric_proof} exploits off-diagonal symmetry to reduce to univariate analysis---a strategy that does not extend to general $K{\geq}3$ column-stochastic structures. We therefore state a conjecture supported by numerical evidence:
106	
107	\begin{conjecture}[$\varepsilon$-approximate envelope monotonicity]
108	\label{conj:monotone}
109	For general $K{\geq}3$ non-IV topologies under $C(\delta) = (1{-}\delta)I + \delta C_0$, $|B(C(\delta))|$ is $\varepsilon$-approximately monotonic with $\varepsilon < 0.02$ for $|\beta| \leq 1$, scaling with effect magnitude (Table~\ref{tab:conjecture_verify},~\ref{tab:dgp_sensitivity}; Appendix~\ref{sec:conjecture_verify}). The safe/fragile partition---five sign-preserving topologies versus exposure and IV---is robust across all tested parameterizations.
110	\end{conjecture}
111	
112	Conjecture~\ref{conj:monotone} is supported by 100{,}000 Dirichlet-sampled matrices and 545{,}945 adversarial curves across four structural families (Appendix~\ref{app:adversarial_monotonicity}), with maximum observed violation $\varepsilon < 0.017$.
113	
114	\begin{remark}[ASV and E-values as complementary tools]
115	\label{rem:evalue}
116	ASV diagnostics and E-values~\cite{vanderweele_ding2017} address orthogonal bias sources---annotation error vs.\ unmeasured confounding---and are most valuable jointly (Table~\ref{tab:sensitivity_comparison}, Appendix). Key distinctions: ASV is topology-dependent (same $C$ has different consequences across topologies); sign-flip ASV targets a failure mode absent from confounding analysis; ASV searches the column-stochastic polytope while E-values optimize over $[1,\infty)$.
117	\end{remark}
118	
119	Under alternating-sign effects ($\boldsymbol{\beta}{=}[0,\,1.0,\,-0.5]$), magnitude ASV ranges from 0.09 (exposure) to $\infty$ (M-bias), a $4{\times}$ difference determined by topology (Table~\ref{tab:asv_stability}). Sign-flip ASV $< 1$ flags sign-reversal-prone pairs; magnitude ASV $< \delta_{\text{observed}}$ indicates bias exceeds tolerance (Algorithm~\ref{alg:correction}); the safe/fragile partition is stable across parameterizations ($\varepsilon < 0.02$; Appendix~\ref{sec:asv_stability}).
120	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "23f39202-bcd7-4d11-8c5c-91968c130168",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "ead2d8d8-c256-449d-857c-70067a205d33",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Setup and Notation}\n\\label{sec:notation}\n\nLet $A$ denote a true $K$-class categorical variable (e.g., sentiment with $K{=}3$ levels) and $A^*$ its observed, potentially misclassified version produced by an LLM annotator. The misclassification process is characterized by a $K{\\times}K$ confusion matrix $C$ with entries $C_{jk} = P(A^*{=}j \\mid A{=}k)$, where each column sums to one (column-stochastic: each column gives the distribution of predicted labels for a given true label). Following \\citet{hernan_cole2009}, we represent this measurement process using \\emph{starred-node} DAGs: the true variable $A$ is latent, and the observed $A^*$ is connected to $A$ via a dashed measurement edge.\n\n\\paragraph{Notation conventions.}\nOur analysis characterizes probability limits (plim, $N \\to \\infty$) rather than finite-sample variance. The FWL theorem~\\cite{frisch1933partial} guarantees that each regression coefficient equals the coefficient from a simple regression after residualizing all other variables---this is why matrix-based corrections fail for covariate topologies (Section~\\ref{sec:correction}). Table~\\ref{tab:notation} (Appendix~\\ref{app:notation_table}) collects all notation.\n\n\\begin{definition}[Non-differential misclassification]\n\\label{def:nondiff}\nMisclassification of $A$ is non-differential with respect to outcome $Y$ and covariates $\\mathbf{Z}$ if $P(A^*{=}j \\mid A{=}k, Y, \\mathbf{Z}) = P(A^*{=}j \\mid A{=}k) = C_{jk}$ for all $j,k$.\n\\end{definition}\n\nIn batch annotation pipelines, the LLM processes each text independently without access to $Y$, making non-differentiality an architectural invariant~\\cite{ziems2024can}; Y-stratified permutation tests confirm this (1/12 rejection at $\\alpha{=}0.05$; Appendix~\\ref{sec:y_stratified_test}). Non-differentiality holds architecturally when $Y$ is external to the annotated text (e.g., health outcomes, voting behavior), since the LLM cannot condition on unobserved $Y$; it may be violated when $Y$ correlates with text content (e.g., topic), in which case the Y-stratified test (Appendix~\\ref{sec:y_stratified_test}) provides empirical verification. Under stress testing, sign reversal occurs in 14/16 $K{\\geq}3$ exposure configurations at $\\varepsilon{=}0.01$ structured departure, with sign-flip rate increasing from 2.0\\% to 9.67\\% at $\\varepsilon{=}0.20$ (Appendix~\\ref{sec:nondiff_stress}); formal degradation guarantees under differential misclassification remain an open problem.\n\nThroughout, $\\tau$ denotes the causal estimand of interest, whose definition varies by topology: the confounder's coefficient, the treatment effect, the indirect effect, or the Wald ratio (Appendix~\\ref{app:confounding}ff.).\n\nWe study seven canonical DAG topologies (Figure~\\ref{fig:dag_taxonomy})~\\cite{pearl2009, hernan2020causal} in which $A$ occupies structurally distinct causal roles: confounder, exposure, mediator, collider, M-bias variable, front-door mediator, and instrument. Throughout, we derive probability limits under \\emph{linear} structural equation models~\\cite{carroll2006}, the standard framework for exact characterization of topology-dependent bias; robustness under logistic regression~\\cite{stefanski_carroll1985} is verified in Appendix~\\ref{sec:logistic_dgp} and~\\ref{sec:fwl_nonlinear}.\n\n\\subsection{Multi-Class Bias Expressions}\n\\label{sec:bias_expressions}\n\nFor each topology, we derive the $\\text{plim}$\\footnote{The probability limit (plim) is the value to which an estimator converges as sample size $N \\to \\infty$; it characterizes systematic bias separately from sampling variability.} of the naive estimator that substitutes $A^*$ for $A$. Let $\\tau$ denote the target causal parameter---its precise definition is topology-specific (e.g., the coefficient on $X$ for confounding, the category-specific $\\beta_j$ for exposure, or the direct effect $\\tau_{\\text{direct}}$ for mediation)---and $\\hat{\\tau}(A^*)$ the estimator using misclassified annotations.\n\n\\paragraph{Confounding ($A$ = confounder).}\nWhen $A$ confounds the $X{\\to}Y$ relationship, the OLS estimator controlling for $A^*$ has probability limit\n\\begin{equation}\n\\label{eq:confounding}\n\\text{plim}\\;\\hat{\\tau}(A^*) = \\bigl(\\mathbb{E}[Z^{\\prime}Z]\\bigr)^{-1}\\mathbb{E}[Z^{\\prime}X]\\,\\boldsymbol{\\beta},\n\\end{equation}\nwhere $Z = [X, \\text{dummies}(A^*)]$, $\\boldsymbol{\\beta}$ contains the true coefficients, and the target parameter $\\tau$ is the coefficient on $X$. Misclassification produces residual confounding that monotonically approaches the omitted variable bias, but the sign of $\\hat{\\tau}$ is preserved: $\\tau_{\\text{sign\\_flip}} = 0$ structurally.\\footnote{Consistent with \\citet{brenner1993}: misclassification degrades confounding control, producing amplification ($|\\hat{\\tau}| > |\\tau|$, universal in this topology) but never sign reversal ($\\text{sign}(\\hat{\\tau}) \\neq \\text{sign}(\\tau)$).}\n\n\\paragraph{Exposure ($A$ = treatment variable).}\nWhen $A$ is the exposure of interest, the biased coefficient for category $j$ becomes a weighted combination of true coefficients:\n\\begin{equation}\n\\label{eq:exposure}\n\\text{plim}\\;\\hat{\\beta}_j(A^*) = \\sum_{k=1}^{K} w_{jk}\\,\\beta_k,\n\\end{equation}\nwhere $w_{jk}$ depends on the confusion matrix $C$ and the population marginal $\\pi_k = P(A{=}k)$. Unlike the binary case, where non-differential misclassification guarantees attenuation toward the null~\\cite{brenner1993}, the $K{\\geq}3$ case permits $w_{jk}$ to assign negative weight to categories with opposite-sign coefficients, producing \\emph{sign reversal}. A near-permutation confusion matrix effectively swaps category labels, making sign reversal the dominant outcome (83.4\\% under uniform Dirichlet prior). This failure mode is structurally impossible at $K{=}2$ because a $2{\\times}2$ stochastic matrix with positive diagonal cannot reverse the sign of a single coefficient.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.92\\textwidth,height=0.18\\textheight,keepaspectratio]{fig2_bias_distribution.pdf}\n\\vspace{-6pt}\n\\caption{Bias distributions under 100{,}000 random $K{=}3$ confusion matrices (uniform Dirichlet; realistic-accuracy results in Section~\\ref{sec:taxonomy_results}). Red = sign reversal. Exposure: 83.4\\% sign reversal; IV: 52.6\\%.}\n\\label{fig:bias_distribution}\n\\end{figure*}\n\n\\paragraph{Numerical Verification 2: Primary coefficient preservation.}\nAcross 23 empirical LLM configurations, the primary coefficient (the category with the largest true effect $|\\beta_k|$) never reverses sign, while 61\\% reverse a secondary (non-dominant) coefficient---confirmed under 100{,}000 Dirichlet matrices with diagonal ${\\geq}\\,0.7$ across six beta-ratio conditions (1.0 to 50.0) with 0\\% primary sign-flip (Appendix~\\ref{app:exposure}).\n\n\\paragraph{Mediation ($A$ = mediator).}\nWhen $A$ mediates the $X{\\to}Y$ relationship~\\cite{vanderweele2015explanation}, the direct effect estimator controlling for $A^*$ has probability limit\n\\begin{equation}\n\\label{eq:mediation}\n\\text{plim}\\;\\hat{\\tau}_{\\text{direct}}(A^*) = \\tau_{\\text{direct}} + \\bigl(1 - \\lambda(C)\\bigr)\\,\\tau_{\\text{indirect}},\n\\end{equation}\nwhere $\\lambda(C) \\in [0,1]$ under proportional effects (Appendix~\\ref{app:proof}, Proposition~\\ref{prop:lambda_bound}), with $\\lambda(I) = 1$ under perfect classification. Misclassification ($\\lambda < 1$) causes the residual indirect effect to be absorbed into the direct path estimate, producing upward bias in $|\\hat{\\tau}_{\\text{direct}}|$ but preserving the sign ($\\tau_{\\text{sign\\_flip}} = 0$).\n\n\\paragraph{Collider, M-bias, and front-door.}\nThree topologies exhibit \\emph{protective} or \\emph{immune} behavior. \\textbf{Collider:} conditioning on $A^*$ instead of $A$ attenuates the spurious path, so annotation error reduces collider bias ($\\tau_{\\text{sign\\_flip}} = 0$). \\textbf{M-bias:} in the M-shaped DAG~\\cite{greenland2003}, misclassifying $A$ weakens the M-bias path; this topology is immune ($\\text{ASV} = \\infty$). \\textbf{Front-door:} the front-door estimator~\\cite{bellemare_bloem2024} is attenuated in both $X \\to A$ and $A \\to Y$ stages, producing moderate bias with $\\tau_{\\text{sign\\_flip}} = 0$.\n\n\\paragraph{Instrumental variable ($A$ = instrument).}\nThe Wald estimator~\\cite{angrist_imbens1995} $\\hat{\\tau}_{\\text{IV}} = \\hat{\\text{cov}}(A^*, Y) / \\hat{\\text{cov}}(A^*, X)$ has $C$ in the denominator. Misclassification can drive first-stage coefficients toward zero or reverse their sign; under random Dirichlet matrices, 52.6\\% produce sign reversal, making IV the most fragile topology (Appendix~\\ref{sec:iv_dirichlet_subspace}).\n\n\\paragraph{Structural sign-flip guarantee.}\n\\begin{proposition}[Sign preservation---analytic results]\n\\label{prop:signflip}\nUnder non-differential misclassification with $C_{kk} > 0$ for all $k$:\n\\emph{(a)}~Confounding preserves sign when $\\operatorname{sign}(\\tau) = \\operatorname{sign}(\\tau {+} B_{\\mathrm{OV}})$, where $B_{\\mathrm{OV}} {=} \\operatorname{Cov}(g(A),f(A))/\\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\\ref{app:confounding}).\n\\emph{(b)}~Collider preserves sign when $|\\tau| > \\sqrt{\\operatorname{Var}(g)\\operatorname{Var}(h)}/\\mathbb{E}[\\operatorname{Var}(T{\\mid}A)]$ (Berkson attenuation; Appendix~\\ref{app:collider}); empirically verified across 100{,}000 matrices with zero violations.\n\\emph{(c)}~Exposure can produce sign reversal for $K {\\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\\ref{app:exposure}).\n\\end{proposition}\n\nSign preservation for non-exposure topologies holds under topology-specific conditions (Table~\\ref{tab:sign_conditions}, Appendix~\\ref{app:conditions}), verified across 100{,}000 random matrices with zero violations; analytic proofs for general $K$ remain open.\n\n\\subsection{Annotation Sensitivity Values}\n\\label{sec:asv}\n\nWe adapt the sensitivity analysis paradigm---E-values~\\cite{vanderweele_ding2017}, partial-$R^2$ bounds~\\cite{cinelli2020making}, coefficient stability~\\cite{oster2019}---to $K{\\times}K$ annotation error, defining Annotation Sensitivity Values (ASVs): we prove $\\varepsilon$-approximate monotonicity along $C(\\delta)$ (Theorem~\\ref{thm:monotone}), reducing $K^2$ dimensions to a scalar; define three ASV diagnostics for topology-dependent failure modes; and combine ASVs with FWL invariance to route corrections.\n\n\\paragraph{Parameterization.}\nWe set $C(\\delta) = (1{-}\\delta)I + \\delta C_0$, where $C_0$ is a reference confusion matrix and $\\delta \\in [0,1]$ controls severity ($\\delta{=}0$: perfect; $\\delta{=}1$: matches $C_0$). This linear path is one of many in the column-stochastic polytope from $I$ to $C_0$; ASV thresholds are path-dependent, but our bootstrap procedure (Section~\\ref{sec:asv_results}) captures estimation uncertainty along the empirical path. We recommend bootstrapping $C_0$ and reporting ASV confidence intervals (Appendix~\\ref{sec:bootstrap_asv}).\n\\paragraph{Three ASV types.}\nWe define three complementary measures: (1)~\\textbf{Magnitude ASV} $\\delta^*_{\\text{mag}} = \\min\\{\\delta : |\\text{plim}\\;\\hat{\\tau}(C(\\delta)) - \\tau| > \\epsilon\\}$---analogous to E-values; (2)~\\textbf{Significance ASV} $\\delta^*_{\\text{sig}} = \\min\\{\\delta : |\\text{plim}\\;\\hat{\\tau}(C(\\delta))| < z_{\\alpha/2} \\cdot SE(N)\\}$---relevant for attenuating topologies; (3)~\\textbf{Sign-flip ASV} $\\delta^*_{\\text{sf}} = \\min\\{\\delta : \\text{sign}(\\hat{\\tau}) \\neq \\text{sign}(\\tau)\\}$---exposure and IV only. The significance ASV depends on $N$ through $SE(N)$, exhibiting a sharp phase transition at a critical $N^*$ below which all rejections are blocked.\n\n\\begin{theorem}[Envelope monotonicity---$K{=}2$]\n\\label{thm:monotone}\nFor $K{=}2$ confounding and mediation topologies with proportional effects ($f = \\lambda g$ for some scalar $\\lambda$) under $C(\\delta) = (1{-}\\delta)I + \\delta C_0$ with $(C_0)_{jj} \\geq \\tfrac{1}{2}$, $|B(C(\\delta))|$ is monotonically non-decreasing in $\\delta \\in [0,1]$.\n\\end{theorem}\n\nThe proof (Appendix~\\ref{app:monotonicity_proof},~\\ref{par:med_monotone}) exploits perspective function convexity; $(C_0)_{jj}{\\geq}\\tfrac{1}{2}$ excludes degenerate matrices. Proportional effects ($f{=}\\lambda g$) is plausible when overall annotation competence drives both paths (e.g., a single quality dimension); it may fail under multi-dimensional asymmetric confusion where different error modes affect $f$ and $g$ differentially. All 23 empirical configurations preserve sign under this assumption, with 97.3\\% preserving sign under non-proportional effects (Appendix~\\ref{sec:proportional_effects}; Tables~\\ref{tab:proportional_effects},~\\ref{tab:proportional_empirical}).\n\n\\begin{theorem}[$K{=}3$ symmetric monotonicity]\n\\label{thm:k3_symmetric}\nFor $K{=}3$ with symmetric confusion matrix $C_{jk} = c$ for $j \\neq k$ and $C_{kk} = 1{-}2c$, $c \\in (0, 1/3)$, and proportional effects ($f{=}\\lambda g$), envelope monotonicity holds exactly: $|B(C(\\delta))|$ is strictly monotone in $\\delta$ for confounding, mediation, and collider topologies whenever $\\mathrm{Var}(g) > 0$.\n\\end{theorem}\n\nTheorem~\\ref{thm:k3_symmetric} serves as a theoretical anchor: exact monotonicity is achievable at $K{=}3$ under symmetric $C_0$. For general asymmetric matrices (empirical $K{=}3$ median $d_{\\mathrm{rel}}{=}0.33$; Remark~\\ref{rem:symmetry}), Conjecture~\\ref{conj:monotone} provides numerical coverage ($\\varepsilon < 0.017$). The proof (Appendix~\\ref{app:k3_symmetric_proof}) exploits the one-parameter reduction $s = c\\delta$ to show $dV_B/ds < 0$ pointwise; under non-proportional effects, approximate monotonicity holds ($\\varepsilon < 0.005$; Appendix~\\ref{app:k3_symmetric_proof}, Remark~2).\n\n\\paragraph{From proofs to numerical evidence.}\nTheorems~\\ref{thm:monotone}--\\ref{thm:k3_symmetric} establish exact monotonicity for $K{=}2$ and $K{=}3$ symmetric matrices. The factorization in Appendix~\\ref{app:k3_symmetric_proof} exploits off-diagonal symmetry to reduce to univariate analysis---a strategy that does not extend to general $K{\\geq}3$ column-stochastic structures. We therefore state a conjecture supported by numerical evidence:\n\n\\begin{conjecture}[$\\varepsilon$-approximate envelope monotonicity]\n\\label{conj:monotone}\nFor general $K{\\geq}3$ non-IV topologies under $C(\\delta) = (1{-}\\delta)I + \\delta C_0$, $|B(C(\\delta))|$ is $\\varepsilon$-approximately monotonic with $\\varepsilon < 0.02$ for $|\\beta| \\leq 1$, scaling with effect magnitude (Table~\\ref{tab:conjecture_verify},~\\ref{tab:dgp_sensitivity}; Appendix~\\ref{sec:conjecture_verify}). The safe/fragile partition---five sign-preserving topologies versus exposure and IV---is robust across all tested parameterizations.\n\\end{conjecture}\n\nConjecture~\\ref{conj:monotone} is supported by 100{,}000 Dirichlet-sampled matrices and 545{,}945 adversarial curves across four structural families (Appendix~\\ref{app:adversarial_monotonicity}), with maximum observed violation $\\varepsilon < 0.017$.\n\n\\begin{remark}[ASV and E-values as complementary tools]\n\\label{rem:evalue}\nASV diagnostics and E-values~\\cite{vanderweele_ding2017} address orthogonal bias sources---annotation error vs.\\ unmeasured confounding---and are most valuable jointly (Table~\\ref{tab:sensitivity_comparison}, Appendix). Key distinctions: ASV is topology-dependent (same $C$ has different consequences across topologies); sign-flip ASV targets a failure mode absent from confounding analysis; ASV searches the column-stochastic polytope while E-values optimize over $[1,\\infty)$.\n\\end{remark}\n\nUnder alternating-sign effects ($\\boldsymbol{\\beta}{=}[0,\\,1.0,\\,-0.5]$), magnitude ASV ranges from 0.09 (exposure) to $\\infty$ (M-bias), a $4{\\times}$ difference determined by topology (Table~\\ref{tab:asv_stability}). Sign-flip ASV $< 1$ flags sign-reversal-prone pairs; magnitude ASV $< \\delta_{\\text{observed}}$ indicates bias exceeds tolerance (Algorithm~\\ref{alg:correction}); the safe/fragile partition is stable across parameterizations ($\\varepsilon < 0.02$; Appendix~\\ref{sec:asv_stability}).\n",
      "numLines": 120,
      "startLine": 1,
      "totalLines": 120
    }
  },
  "sourceToolAssistantUUID": "23f39202-bcd7-4d11-8c5c-91968c130168",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-24T06:35:30.263Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Uz7yKvY65toJyKJQGoR5aH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ead2d8d8-c256-449d-857c-70067a205d33",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "8cf6e669-846b-4567-a098-b156379b5322",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 18 · 2026-05-24T06:35:30.269Z_

<details><summary>↩ Tool result · `toolu_01Uz7yKvY65toJyKJQGoR5aH`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We validate through Monte Carlo simulation ($K{=}3$), cross-$K$ robustness checks ($K{=}5,7$), and empirical validation with real LLM confusion matrices from three NLP tasks ($K{=}2,3,10$).
5	
6	\subsection{Setup}
7	\label{sec:setup}
8	
9	For each topology, we sample 100{,}000 confusion matrices from a Dirichlet$(1,1,1)$ prior, compute analytical probability limits, and validate against Monte Carlo simulation ($N{=}10{,}000$). ASV experiments use $C(\delta) = (1{-}\delta)I + \delta C_0$.
10	
11	\subsection{Bias Taxonomy}
12	\label{sec:taxonomy_results}
13	
14	\paragraph{Theory-MC agreement.}
15	Analytical probability limits match Monte Carlo estimates with MAPE of 1.6\%, averaged across 161 scenarios (23 LLM configurations $\times$ 7 topologies; per-topology range: 0.3\%--3.7\%).
16	
17	\paragraph{Exposure DAG: sign reversal under multi-class misclassification.}
18	Under realistic accuracy (diagonal $\geq 0.7$), the violation rate is 13.7\% with 2.1\% sign reversal; at diagonal $\geq 0.9$, violation persists at 11.9\% (Appendix~\ref{sec:iv_dirichlet_subspace}). Under the full Dirichlet prior, 85\% of matrices violate the binary ``toward-null'' guarantee and 83.4\% cause sign reversal; $\min_k C_{kk} < 0.55$ predicts sign reversal with 91\% accuracy (Appendix~\ref{sec:sign_determinants}). The $K{=}2$ control confirms classical attenuation~\cite{brenner1993}, establishing the multi-class failure as structurally distinct.
19	
20	\paragraph{Structural guarantee for non-exposure topologies.}
21	Five topologies exhibit zero sign-flip rate (Table~\ref{tab:taxonomy}): confounding, mediation, and front-door show 100\% amplification~\cite{brenner1993, dosemeci1990} but never reverse the sign; collider is protective ($|B(C)|$ non-increasing; Conjecture~\ref{conj:monotone}); M-bias shows weakest sensitivity (53.2\% violation). All patterns persist at $K{=}5,7$ (Appendix~\ref{sec:cross_k_robustness}).
22	
23	\paragraph{IV: Wald estimator instability.}
24	The IV topology is the sole non-exposure exception: 52.6\% of random matrices cause sign reversal, stable across $K{=}3,5,7$. Diagonal dominance ($C_{kk} > 0.5$) eliminates sign reversal but preserves amplification (Appendix~\ref{sec:iv_dirichlet_subspace}); however, all 23 empirical LLM configurations show zero IV sign reversal.
25	
26	\begin{table}[t]
27	\centering
28	\caption{Bias under $K{=}3$ non-differential misclassification (100{,}000 Dirichlet$(1,1,1)$ matrices). Violation: $|\text{bias}| > 0$; Sign Flip: any coefficient reverses sign; Amplif.: $|\hat{\tau}| > |\tau|$. $\tau_{\text{sf}}{=}0$?: sign-flip guarantee holds unconditionally (Yes), conditionally (Cond.; Proposition~\ref{prop:signflip}), or not (No). Collider 100\% amplification reflects Berkson bias---misclassification is protective.}
29	\label{tab:taxonomy}
30	\small
31	\begin{tabular}{lcccc}
32	\toprule
33	\textbf{Topology} & \textbf{Violation} & \textbf{Sign Flip} & \textbf{Amplif.} & $\tau_{\text{sf}}{=}0$? \\
34	\midrule
35	Confounding & 100\% & 0\% & 100\% & Cond. \\
36	Exposure & 85\% & 83.4\% & 14.1\% & No \\
37	Mediation & 100\% & 0\% & 100\% & Cond. \\
38	Front-door & 100\% & 0\% & 100\% & Cond. \\
39	Collider & 100\% & 0\% & 100\% & Cond. \\
40	M-bias & 53.2\% & 0\% & 10.4\% & Yes \\
41	IV & 100\% & 52.6\% & 100\% & No \\
42	\bottomrule
43	\end{tabular}
44	\end{table}
45	
46	The bias distributions are visualized in Figure~\ref{fig:bias_distribution}.
47	
48	\subsection{ASV Framework Validation}
49	\label{sec:asv_results}
50	
51	\begin{figure}[t]
52	\centering
53	\includegraphics[width=\columnwidth]{fig3_asv_ranking.pdf}
54	\caption{ASV vulnerability ranking across topologies. Three ASV types (magnitude, significance, sign-flip) reveal a topology-dependent spectrum from IV (maximally fragile) to M-bias (immune, ASV $= \infty$).}
55	\label{fig:asv_ranking}
56	\end{figure}
57	
58	\paragraph{ASV results.}
59	The ASV envelope is $\varepsilon$-approximately monotonic for non-IV topologies ($\varepsilon < 0.02$ for non-exposure under moderate effects, larger for exposure; Conjecture~\ref{conj:monotone}). Figure~\ref{fig:asv_ranking} shows the vulnerability ranking: IV is maximally fragile, M-bias is immune ($\text{ASV} = \infty$). Sign-flip ASV: 83.4\% of exposure matrices yield $\delta^*_{\text{sf}} < 1$; IV ranges 1.1--6.7 (Table~\ref{tab:asv_grid}). Significance ASV exhibits a phase transition at $N^* \approx 6{,}000$--$10{,}000$; bootstrap CIs ($B{=}1{,}000$; Appendix~\ref{sec:bootstrap_asv}) confirm stable topology ranking despite wide IV intervals.
60	
61	\subsection{Empirical Validation}
62	\label{sec:empirical}
63	
64	We validate using real LLM confusion matrices from HumAID~\cite{alam2021humaid} ($K{=}10$), VAST ($K{=}3$), and CivilComments ($K{=}2$): four LLMs, 23 configurations, 161 bias scenarios.
65	
66	\paragraph{Empirical bias ranking.}
67	HumAID ($K{=}10$) matches predictions: IV (12.4--42.1\%) and exposure (9.0--17.4\%) dominate; remaining topologies $<$15\%. $F_1$ shows no rank correlation with bias ($\rho = -0.10$, $p = 0.45$; Figure~\ref{fig:f1_vs_bias}), but per-topology patterns diverge: five topologies show $F_1{\uparrow}{\to}\text{bias}{\downarrow}$ ($\rho \leq -0.53$), while M-bias reverses ($\rho = 0.87$; Appendix~\ref{sec:within_topo_f1}). Of exposure coefficients, 14/23 (61\%) exhibit sign reversal---all secondary; zero across 138 non-exposure scenarios.
68	
69	\begin{figure}[t]
70	\centering
71	\includegraphics[width=\columnwidth]{fig5_f1_vs_bias.pdf}
72	\caption{Topology determines downstream causal bias, not $F_1$. HumAID $K{=}10$ (56 points): within $F_1$ range 0.614--0.690, bias varies $10{\times}$ (IV 42.1\% vs.\ collider $<$5.6\%).}
73	\label{fig:f1_vs_bias}
74	\end{figure}
75	
76	
77	\subsection{Correction Guidance}
78	\label{sec:correction}
79	
80	We evaluate five correction methods (naive plug-in, MLA, DSL~\cite{egami_hinck_stewart_wei2023}, MC-SIMEX~\cite{kuchenhoff2006simex}, PPI++~\cite{angelopoulos2023}) across all topologies (210 configurations; Table~\ref{tab:correction}, Appendix~\ref{app:supplementary}). Regression calibration~\cite{carroll2006} is designed for continuous measurement error and does not apply to categorical misclassification.
81	
82	\paragraph{FWL invariance (observation).}
83	FWL invariance implies matrix-based methods (naive plug-in, MLA) achieve 0\% bias reduction for covariate topologies (Appendix~\ref{app:fwl_proof}); under logistic regression this breaks but ranking persists ($|\Delta| < 0.02$; Appendix~\ref{sec:fwl_nonlinear}). To our knowledge, this futility result---that matrix-based corrections cannot reduce covariate-induced bias under FWL decomposition---has not been explicitly stated in the measurement error literature~\cite{carroll2006, buonaccorsi2010}.
84	
85	\paragraph{Method ranking.}
86	PPI++ achieves the highest RMSE reduction (47.0\% at $K{=}3$) but requires gold labels and harms M-bias ($-$88\%); MC-SIMEX is gold-free and $K$-robust (27--70\%), though it harms front-door ($-$62.4\%); rankings are stable across $K$ ($\rho \geq 0.80$; Appendix~\ref{sec:correction_k_sensitivity}).
87	
88	\paragraph{Correction decision procedure.}
89	Given topology $\mathcal{T}$ and gold-label availability: (1)~\textbf{Risk:} M-bias $\to$ low; confounding/mediation/collider/front-door $\to$ medium; exposure/IV $\to$ high. (2)~\textbf{Method:} with gold, PPI++ except M-bias; without gold, DSL for confounding/mediation, MC-SIMEX for IV/collider. (3)~\textbf{FWL:} skip plug-in/MLA for covariate topologies (0\% reduction). If $\mathcal{T}$ uncertain, compute ASV under candidate topologies and report worst-case sensitivity (Algorithm~\ref{alg:correction}, Appendix~\ref{app:supplementary}).
90	
91	\paragraph{Case studies and sensitivity.}
92	ClinicalBERT and HumAID ($K{=}10$) confirm all patterns---FWL invariance, PPI++ harm for M-bias/IV, partition recoverability---under linear and logistic models ($|\Delta| < 0.02$; Appendix~\ref{app:case_study},~\ref{sec:correction_k_sensitivity}). An end-to-end demo ($K{=}3$, $N{=}10{,}000$, 100 replicates; Table~\ref{tab:e2e-demo}) confirms: confounding achieves 0\% improvement (FWL), PPI++ reduces exposure bias from 42.9\% to 0.2\%, while topology-agnostic IV correction amplifies bias ($-$139\%). A semi-real study with 10 VAST matrices ($d_{\mathrm{rel}} = 0.30$--$0.38$) confirms: 93.6\% median exposure bias reduction, 0\% confounding improvement (Appendix~\ref{sec:real_cm_demo}).
93	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8cf6e669-846b-4567-a098-b156379b5322",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "db0488e1-1420-428b-b348-78a3eb84160b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe validate through Monte Carlo simulation ($K{=}3$), cross-$K$ robustness checks ($K{=}5,7$), and empirical validation with real LLM confusion matrices from three NLP tasks ($K{=}2,3,10$).\n\n\\subsection{Setup}\n\\label{sec:setup}\n\nFor each topology, we sample 100{,}000 confusion matrices from a Dirichlet$(1,1,1)$ prior, compute analytical probability limits, and validate against Monte Carlo simulation ($N{=}10{,}000$). ASV experiments use $C(\\delta) = (1{-}\\delta)I + \\delta C_0$.\n\n\\subsection{Bias Taxonomy}\n\\label{sec:taxonomy_results}\n\n\\paragraph{Theory-MC agreement.}\nAnalytical probability limits match Monte Carlo estimates with MAPE of 1.6\\%, averaged across 161 scenarios (23 LLM configurations $\\times$ 7 topologies; per-topology range: 0.3\\%--3.7\\%).\n\n\\paragraph{Exposure DAG: sign reversal under multi-class misclassification.}\nUnder realistic accuracy (diagonal $\\geq 0.7$), the violation rate is 13.7\\% with 2.1\\% sign reversal; at diagonal $\\geq 0.9$, violation persists at 11.9\\% (Appendix~\\ref{sec:iv_dirichlet_subspace}). Under the full Dirichlet prior, 85\\% of matrices violate the binary ``toward-null'' guarantee and 83.4\\% cause sign reversal; $\\min_k C_{kk} < 0.55$ predicts sign reversal with 91\\% accuracy (Appendix~\\ref{sec:sign_determinants}). The $K{=}2$ control confirms classical attenuation~\\cite{brenner1993}, establishing the multi-class failure as structurally distinct.\n\n\\paragraph{Structural guarantee for non-exposure topologies.}\nFive topologies exhibit zero sign-flip rate (Table~\\ref{tab:taxonomy}): confounding, mediation, and front-door show 100\\% amplification~\\cite{brenner1993, dosemeci1990} but never reverse the sign; collider is protective ($|B(C)|$ non-increasing; Conjecture~\\ref{conj:monotone}); M-bias shows weakest sensitivity (53.2\\% violation). All patterns persist at $K{=}5,7$ (Appendix~\\ref{sec:cross_k_robustness}).\n\n\\paragraph{IV: Wald estimator instability.}\nThe IV topology is the sole non-exposure exception: 52.6\\% of random matrices cause sign reversal, stable across $K{=}3,5,7$. Diagonal dominance ($C_{kk} > 0.5$) eliminates sign reversal but preserves amplification (Appendix~\\ref{sec:iv_dirichlet_subspace}); however, all 23 empirical LLM configurations show zero IV sign reversal.\n\n\\begin{table}[t]\n\\centering\n\\caption{Bias under $K{=}3$ non-differential misclassification (100{,}000 Dirichlet$(1,1,1)$ matrices). Violation: $|\\text{bias}| > 0$; Sign Flip: any coefficient reverses sign; Amplif.: $|\\hat{\\tau}| > |\\tau|$. $\\tau_{\\text{sf}}{=}0$?: sign-flip guarantee holds unconditionally (Yes), conditionally (Cond.; Proposition~\\ref{prop:signflip}), or not (No). Collider 100\\% amplification reflects Berkson bias---misclassification is protective.}\n\\label{tab:taxonomy}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Violation} & \\textbf{Sign Flip} & \\textbf{Amplif.} & $\\tau_{\\text{sf}}{=}0$? \\\\\n\\midrule\nConfounding & 100\\% & 0\\% & 100\\% & Cond. \\\\\nExposure & 85\\% & 83.4\\% & 14.1\\% & No \\\\\nMediation & 100\\% & 0\\% & 100\\% & Cond. \\\\\nFront-door & 100\\% & 0\\% & 100\\% & Cond. \\\\\nCollider & 100\\% & 0\\% & 100\\% & Cond. \\\\\nM-bias & 53.2\\% & 0\\% & 10.4\\% & Yes \\\\\nIV & 100\\% & 52.6\\% & 100\\% & No \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe bias distributions are visualized in Figure~\\ref{fig:bias_distribution}.\n\n\\subsection{ASV Framework Validation}\n\\label{sec:asv_results}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_asv_ranking.pdf}\n\\caption{ASV vulnerability ranking across topologies. Three ASV types (magnitude, significance, sign-flip) reveal a topology-dependent spectrum from IV (maximally fragile) to M-bias (immune, ASV $= \\infty$).}\n\\label{fig:asv_ranking}\n\\end{figure}\n\n\\paragraph{ASV results.}\nThe ASV envelope is $\\varepsilon$-approximately monotonic for non-IV topologies ($\\varepsilon < 0.02$ for non-exposure under moderate effects, larger for exposure; Conjecture~\\ref{conj:monotone}). Figure~\\ref{fig:asv_ranking} shows the vulnerability ranking: IV is maximally fragile, M-bias is immune ($\\text{ASV} = \\infty$). Sign-flip ASV: 83.4\\% of exposure matrices yield $\\delta^*_{\\text{sf}} < 1$; IV ranges 1.1--6.7 (Table~\\ref{tab:asv_grid}). Significance ASV exhibits a phase transition at $N^* \\approx 6{,}000$--$10{,}000$; bootstrap CIs ($B{=}1{,}000$; Appendix~\\ref{sec:bootstrap_asv}) confirm stable topology ranking despite wide IV intervals.\n\n\\subsection{Empirical Validation}\n\\label{sec:empirical}\n\nWe validate using real LLM confusion matrices from HumAID~\\cite{alam2021humaid} ($K{=}10$), VAST ($K{=}3$), and CivilComments ($K{=}2$): four LLMs, 23 configurations, 161 bias scenarios.\n\n\\paragraph{Empirical bias ranking.}\nHumAID ($K{=}10$) matches predictions: IV (12.4--42.1\\%) and exposure (9.0--17.4\\%) dominate; remaining topologies $<$15\\%. $F_1$ shows no rank correlation with bias ($\\rho = -0.10$, $p = 0.45$; Figure~\\ref{fig:f1_vs_bias}), but per-topology patterns diverge: five topologies show $F_1{\\uparrow}{\\to}\\text{bias}{\\downarrow}$ ($\\rho \\leq -0.53$), while M-bias reverses ($\\rho = 0.87$; Appendix~\\ref{sec:within_topo_f1}). Of exposure coefficients, 14/23 (61\\%) exhibit sign reversal---all secondary; zero across 138 non-exposure scenarios.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig5_f1_vs_bias.pdf}\n\\caption{Topology determines downstream causal bias, not $F_1$. HumAID $K{=}10$ (56 points): within $F_1$ range 0.614--0.690, bias varies $10{\\times}$ (IV 42.1\\% vs.\\ collider $<$5.6\\%).}\n\\label{fig:f1_vs_bias}\n\\end{figure}\n\n\n\\subsection{Correction Guidance}\n\\label{sec:correction}\n\nWe evaluate five correction methods (naive plug-in, MLA, DSL~\\cite{egami_hinck_stewart_wei2023}, MC-SIMEX~\\cite{kuchenhoff2006simex}, PPI++~\\cite{angelopoulos2023}) across all topologies (210 configurations; Table~\\ref{tab:correction}, Appendix~\\ref{app:supplementary}). Regression calibration~\\cite{carroll2006} is designed for continuous measurement error and does not apply to categorical misclassification.\n\n\\paragraph{FWL invariance (observation).}\nFWL invariance implies matrix-based methods (naive plug-in, MLA) achieve 0\\% bias reduction for covariate topologies (Appendix~\\ref{app:fwl_proof}); under logistic regression this breaks but ranking persists ($|\\Delta| < 0.02$; Appendix~\\ref{sec:fwl_nonlinear}). To our knowledge, this futility result---that matrix-based corrections cannot reduce covariate-induced bias under FWL decomposition---has not been explicitly stated in the measurement error literature~\\cite{carroll2006, buonaccorsi2010}.\n\n\\paragraph{Method ranking.}\nPPI++ achieves the highest RMSE reduction (47.0\\% at $K{=}3$) but requires gold labels and harms M-bias ($-$88\\%); MC-SIMEX is gold-free and $K$-robust (27--70\\%), though it harms front-door ($-$62.4\\%); rankings are stable across $K$ ($\\rho \\geq 0.80$; Appendix~\\ref{sec:correction_k_sensitivity}).\n\n\\paragraph{Correction decision procedure.}\nGiven topology $\\mathcal{T}$ and gold-label availability: (1)~\\textbf{Risk:} M-bias $\\to$ low; confounding/mediation/collider/front-door $\\to$ medium; exposure/IV $\\to$ high. (2)~\\textbf{Method:} with gold, PPI++ except M-bias; without gold, DSL for confounding/mediation, MC-SIMEX for IV/collider. (3)~\\textbf{FWL:} skip plug-in/MLA for covariate topologies (0\\% reduction). If $\\mathcal{T}$ uncertain, compute ASV under candidate topologies and report worst-case sensitivity (Algorithm~\\ref{alg:correction}, Appendix~\\ref{app:supplementary}).\n\n\\paragraph{Case studies and sensitivity.}\nClinicalBERT and HumAID ($K{=}10$) confirm all patterns---FWL invariance, PPI++ harm for M-bias/IV, partition recoverability---under linear and logistic models ($|\\Delta| < 0.02$; Appendix~\\ref{app:case_study},~\\ref{sec:correction_k_sensitivity}). An end-to-end demo ($K{=}3$, $N{=}10{,}000$, 100 replicates; Table~\\ref{tab:e2e-demo}) confirms: confounding achieves 0\\% improvement (FWL), PPI++ reduces exposure bias from 42.9\\% to 0.2\\%, while topology-agnostic IV correction amplifies bias ($-$139\\%). A semi-real study with 10 VAST matrices ($d_{\\mathrm{rel}} = 0.30$--$0.38$) confirms: 93.6\\% median exposure bias reduction, 0\\% confounding improvement (Appendix~\\ref{sec:real_cm_demo}).\n",
      "numLines": 93,
      "startLine": 1,
      "totalLines": 93
    }
  },
  "sourceToolAssistantUUID": "8cf6e669-846b-4567-a098-b156379b5322",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-24T06:35:30.897Z_

<details open><summary>🔧 Tool call — Read · `toolu_016yeK2rQmw3Be1pnpcdPhFr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "db0488e1-1420-428b-b348-78a3eb84160b",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "164adf04-d9e2-4140-8a9a-203831ece48d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 20 · 2026-05-24T06:35:30.901Z_

<details><summary>↩ Tool result · `toolu_016yeK2rQmw3Be1pnpcdPhFr`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We characterized how multi-class annotation errors interact with causal DAG topology: at $K{\geq}3$, exposure and IV can reverse treatment effect signs while five topologies preserve them. ASVs yield a topology-dependent vulnerability ranking; matrix-based corrections are provably ineffective under linear regression for four covariate topologies (FWL invariance). The practical implication is direct: identify the topology first---for four topologies, no matrix-based correction helps; for exposure, PPI++ with gold labels reduces bias by 93.6\%.
5	
6	\section*{Limitations}
7	
8	We assume non-differential misclassification (Appendix~\ref{sec:nondiff_stress}). Closed-form results (Theorems~1--2) assume linear SEMs with proportional effects ($f{=}\lambda g$); proportional effects is a reasonable approximation for ordinal classification (e.g., sentiment strength) where treatment shifts the distribution along an ordered scale, and sign preservation holds at 97.3\% under non-proportional effects (Table~\ref{tab:proportional_empirical}). FWL invariance extends to logistic models for covariate topologies (Appendix~\ref{app:fwl_proof}), but for exposure, logistic specification can increase bias (Appendix~\ref{sec:fwl_nonlinear}); practical recommendations do not directly extend to nonlinear models (matching, doubly-robust). The $C(\delta)$ linear interpolation assumes misclassification patterns are structurally stable as error severity varies; LLM quality changes across prompts may not follow this path. ASV computation requires estimating $B_{\mathrm{OV}}$ from gold labels via $C^{-1}$; error propagation under small gold-label budgets ($<$500) is an open question. The framework assumes a known DAG; DAG misspecification under measurement error may compound bias. General $K{\geq}3$ envelope monotonicity remains open; worst-case step deviation reaches 0.056 for exposure but empirically decreases with $K$ ($\varepsilon \propto K^{-\alpha}$, $\alpha \in [0.6, 1.5]$; Table~\ref{tab:conjecture_verify}), and Algorithm~1 routing is robust to violations below $\varepsilon{=}0.017$.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "164adf04-d9e2-4140-8a9a-203831ece48d",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "c2f99aa1-e670-4b28-8d8f-5a6c8c382e41",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe characterized how multi-class annotation errors interact with causal DAG topology: at $K{\\geq}3$, exposure and IV can reverse treatment effect signs while five topologies preserve them. ASVs yield a topology-dependent vulnerability ranking; matrix-based corrections are provably ineffective under linear regression for four covariate topologies (FWL invariance). The practical implication is direct: identify the topology first---for four topologies, no matrix-based correction helps; for exposure, PPI++ with gold labels reduces bias by 93.6\\%.\n\n\\section*{Limitations}\n\nWe assume non-differential misclassification (Appendix~\\ref{sec:nondiff_stress}). Closed-form results (Theorems~1--2) assume linear SEMs with proportional effects ($f{=}\\lambda g$); proportional effects is a reasonable approximation for ordinal classification (e.g., sentiment strength) where treatment shifts the distribution along an ordered scale, and sign preservation holds at 97.3\\% under non-proportional effects (Table~\\ref{tab:proportional_empirical}). FWL invariance extends to logistic models for covariate topologies (Appendix~\\ref{app:fwl_proof}), but for exposure, logistic specification can increase bias (Appendix~\\ref{sec:fwl_nonlinear}); practical recommendations do not directly extend to nonlinear models (matching, doubly-robust). The $C(\\delta)$ linear interpolation assumes misclassification patterns are structurally stable as error severity varies; LLM quality changes across prompts may not follow this path. ASV computation requires estimating $B_{\\mathrm{OV}}$ from gold labels via $C^{-1}$; error propagation under small gold-label budgets ($<$500) is an open question. The framework assumes a known DAG; DAG misspecification under measurement error may compound bias. General $K{\\geq}3$ envelope monotonicity remains open; worst-case step deviation reaches 0.056 for exposure but empirically decreases with $K$ ($\\varepsilon \\propto K^{-\\alpha}$, $\\alpha \\in [0.6, 1.5]$; Table~\\ref{tab:conjecture_verify}), and Algorithm~1 routing is robust to violations below $\\varepsilon{=}0.017$.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  },
  "sourceToolAssistantUUID": "164adf04-d9e2-4140-8a9a-203831ece48d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-24T06:35:31.829Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WNUhnz24CQ2gvGFvHwkgws`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c2f99aa1-e670-4b28-8d8f-5a6c8c382e41",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "b2a6b189-6c68-469c-821f-c5d4a4b6907d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 22 · 2026-05-24T06:35:32.143Z_

<details><summary>↩ Tool result · reported error · `toolu_01WNUhnz24CQ2gvGFvHwkgws`</summary>

```text
File content (46720 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b2a6b189-6c68-469c-821f-c5d4a4b6907d",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "4bf208a1-e361-452f-99aa-33b6211967d4",
  "toolUseResult": "Error: File content (46720 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "b2a6b189-6c68-469c-821f-c5d4a4b6907d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-24T06:35:32.201Z_

<details open><summary>🔧 Tool call — Read · `toolu_015pvC1o9apT4tHwiQzGgbYQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4bf208a1-e361-452f-99aa-33b6211967d4",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "75cff9b9-a0f5-4797-bff1-22e0d3fe35fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-24T06:35:32.205Z_

<details><summary>↩ Tool result · `toolu_015pvC1o9apT4tHwiQzGgbYQ`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Measurement error in causal inference.}
5	Foundations appear in \citet{carroll2006, gustafson2004, buonaccorsi2010, bound2001measurement}, with DAG-based formalization by \citet{hernan_cole2009} and \citet{kuroki_pearl2014}. For binary variables, non-differential misclassification biases toward the null~\cite{bross1954misclassification, brenner1993, ogburn_vanderweele2012}, but this fails for polytomous exposures~\cite{dosemeci1990, jurek2005, veirod_laake2001}. Extensions address differential measurement error~\cite{edwards_lessler_naimi2021, imai_yamamoto2010}, endogenous misreporting~\cite{nguimkeu_denteh_tchernis2019}, mismeasured covariates under IPW~\cite{shu_yi2019a, shu_yi2019b}, mediation with mismeasured mediators~\cite{valeri_vanderweele2013}, nonclassical error~\cite{schennach2020mismeasured}, and multiply robust estimation~\cite{wei2025multiply}. All analyze a single DAG topology; ours characterizes how the \emph{same} confusion matrix produces qualitatively different bias across seven topologies.
6	
7	\paragraph{Text classifiers and LLM annotation.}
8	\citet{grimmer2022} and \citet{feder_etal2022} provide foundations for text-as-data and causal inference in NLP. \citet{wood_doughty2018} first applied DAG reasoning to classifier error; \citet{teblunthuis2024} gave the most complete binary treatment ($K{=}2$, four DAGs); \citet{lee_wood_doughty2024} extended to categorical LLM classifiers but covered only confounding. On annotation quality, \citet{gilardi2023chatgpt} and \citet{ziems2024can} document rapid LLM annotator adoption (surveyed by \citealt{tan2024llm}), \citet{baumann2025} found 31\% incorrect conclusions, and \citet{kim_garg2025} showed 60\% error correlation across models~\cite{pangakis_wolken_fasching2023, cheng_mayya_sedoc2024, variance_aware_llm2026, hidden_measurement_error2026}. \citet{audinet2025} benchmark debiasing; \citet{keith_jensen_oconnor2020} survey the landscape. These works either restrict to binary labels, cover a single topology, or diagnose quality without connecting it to causal validity.
9	
10	\paragraph{Sensitivity analysis and correction methods.}
11	Our ASV framework draws on sensitivity analysis without assumptions~\cite{ding_vanderweele2016}, E-values~\cite{vanderweele_ding2017, mathur2018}, robustness values~\cite{cinelli2020making}, and mediation sensitivity~\cite{imai_keele_yamamoto2010, pryzant_etal2021}, but parametrizes annotation error severity rather than omitted variable strength. \citet{lash2009} and \citet{blackwell_honaker_king2017} provide complementary frameworks; \citet{mahajan2006} and \citet{hu2008} establish identification and estimation under misclassified regressors, including nonlinear models with instrumental variables. For correction, PPI++~\cite{angelopoulos2023} and DSL~\cite{egami_hinck_stewart_wei2023} are topology-agnostic, with extensions by \citet{zrnic_candes2024, demirel2024prediction, cadei2025, gligoric2025}. We show this agnosticism is costly: correction effectiveness is itself topology-dependent, with matrix-based methods provably ineffective under linear FWL decomposition for four topologies.
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "75cff9b9-a0f5-4797-bff1-22e0d3fe35fe",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "fc60b897-db9f-49f0-a7f6-3542ea941af7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Measurement error in causal inference.}\nFoundations appear in \\citet{carroll2006, gustafson2004, buonaccorsi2010, bound2001measurement}, with DAG-based formalization by \\citet{hernan_cole2009} and \\citet{kuroki_pearl2014}. For binary variables, non-differential misclassification biases toward the null~\\cite{bross1954misclassification, brenner1993, ogburn_vanderweele2012}, but this fails for polytomous exposures~\\cite{dosemeci1990, jurek2005, veirod_laake2001}. Extensions address differential measurement error~\\cite{edwards_lessler_naimi2021, imai_yamamoto2010}, endogenous misreporting~\\cite{nguimkeu_denteh_tchernis2019}, mismeasured covariates under IPW~\\cite{shu_yi2019a, shu_yi2019b}, mediation with mismeasured mediators~\\cite{valeri_vanderweele2013}, nonclassical error~\\cite{schennach2020mismeasured}, and multiply robust estimation~\\cite{wei2025multiply}. All analyze a single DAG topology; ours characterizes how the \\emph{same} confusion matrix produces qualitatively different bias across seven topologies.\n\n\\paragraph{Text classifiers and LLM annotation.}\n\\citet{grimmer2022} and \\citet{feder_etal2022} provide foundations for text-as-data and causal inference in NLP. \\citet{wood_doughty2018} first applied DAG reasoning to classifier error; \\citet{teblunthuis2024} gave the most complete binary treatment ($K{=}2$, four DAGs); \\citet{lee_wood_doughty2024} extended to categorical LLM classifiers but covered only confounding. On annotation quality, \\citet{gilardi2023chatgpt} and \\citet{ziems2024can} document rapid LLM annotator adoption (surveyed by \\citealt{tan2024llm}), \\citet{baumann2025} found 31\\% incorrect conclusions, and \\citet{kim_garg2025} showed 60\\% error correlation across models~\\cite{pangakis_wolken_fasching2023, cheng_mayya_sedoc2024, variance_aware_llm2026, hidden_measurement_error2026}. \\citet{audinet2025} benchmark debiasing; \\citet{keith_jensen_oconnor2020} survey the landscape. These works either restrict to binary labels, cover a single topology, or diagnose quality without connecting it to causal validity.\n\n\\paragraph{Sensitivity analysis and correction methods.}\nOur ASV framework draws on sensitivity analysis without assumptions~\\cite{ding_vanderweele2016}, E-values~\\cite{vanderweele_ding2017, mathur2018}, robustness values~\\cite{cinelli2020making}, and mediation sensitivity~\\cite{imai_keele_yamamoto2010, pryzant_etal2021}, but parametrizes annotation error severity rather than omitted variable strength. \\citet{lash2009} and \\citet{blackwell_honaker_king2017} provide complementary frameworks; \\citet{mahajan2006} and \\citet{hu2008} establish identification and estimation under misclassified regressors, including nonlinear models with instrumental variables. For correction, PPI++~\\cite{angelopoulos2023} and DSL~\\cite{egami_hinck_stewart_wei2023} are topology-agnostic, with extensions by \\citet{zrnic_candes2024, demirel2024prediction, cadei2025, gligoric2025}. We show this agnosticism is costly: correction effectiveness is itself topology-dependent, with matrix-based methods provably ineffective under linear FWL decomposition for four topologies.\n",
      "numLines": 12,
      "startLine": 1,
      "totalLines": 12
    }
  },
  "sourceToolAssistantUUID": "75cff9b9-a0f5-4797-bff1-22e0d3fe35fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-24T06:35:32.681Z_

<details open><summary>🔧 Tool call — Read · `toolu_018TpnFADrPrJjQaqhk1XYUW`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fc60b897-db9f-49f0-a7f6-3542ea941af7",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "51e018ac-b86e-41a5-8f03-7f176c9dd064",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 26 · 2026-05-24T06:35:32.685Z_

<details><summary>↩ Tool result · `toolu_018TpnFADrPrJjQaqhk1XYUW`</summary>

```text
1	\begin{abstract}
2	When LLM-generated annotations feed into causal inference, annotation quality is the wrong thing to worry about---the causal DAG topology determines whether errors attenuate, amplify, or reverse the treatment effect estimate. We derive bias expressions for seven canonical topologies under $K$-class non-differential misclassification in linear structural equation models and show that $K {\geq} 3$ introduces a structural possibility of sign reversal absent in the binary case. Under proportional effects, five topologies provably preserve the treatment effect sign; exposure and IV can reverse it. Under empirical LLM confusion matrices, sign reversal is confined to exposure topology. We introduce Annotation Sensitivity Values (ASVs), with proved ($K{=}2$, $K{=}3$ symmetric) and extensively validated (general $K{\geq}3$) monotonicity, yielding a vulnerability ranking from IV (maximally fragile) to M-bias (immune), and show that matrix-based corrections are provably ineffective under linear regression for four topologies due to Frisch--Waugh--Lovell invariance. A case study with 10 production LLM confusion matrices confirms: topology-aware correction reduces exposure bias from 61\% to $<$1\%, while topology-blind corrections are provably futile under linear regression for four topologies.
3	\end{abstract}
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "51e018ac-b86e-41a5-8f03-7f176c9dd064",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "0a33bf23-405e-4b8e-999d-fc50b337d34f",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nWhen LLM-generated annotations feed into causal inference, annotation quality is the wrong thing to worry about---the causal DAG topology determines whether errors attenuate, amplify, or reverse the treatment effect estimate. We derive bias expressions for seven canonical topologies under $K$-class non-differential misclassification in linear structural equation models and show that $K {\\geq} 3$ introduces a structural possibility of sign reversal absent in the binary case. Under proportional effects, five topologies provably preserve the treatment effect sign; exposure and IV can reverse it. Under empirical LLM confusion matrices, sign reversal is confined to exposure topology. We introduce Annotation Sensitivity Values (ASVs), with proved ($K{=}2$, $K{=}3$ symmetric) and extensively validated (general $K{\\geq}3$) monotonicity, yielding a vulnerability ranking from IV (maximally fragile) to M-bias (immune), and show that matrix-based corrections are provably ineffective under linear regression for four topologies due to Frisch--Waugh--Lovell invariance. A case study with 10 production LLM confusion matrices confirms: topology-aware correction reduces exposure bias from 61\\% to $<$1\\%, while topology-blind corrections are provably futile under linear regression for four topologies.\n\\end{abstract}\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  },
  "sourceToolAssistantUUID": "51e018ac-b86e-41a5-8f03-7f176c9dd064",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-24T06:35:33.126Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MgvQ9EHQr4ZcmpFjFtv2yj`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0a33bf23-405e-4b8e-999d-fc50b337d34f",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "1ea9522a-981e-4efa-a334-38de07bb9da0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 28 · 2026-05-24T06:35:33.131Z_

<details><summary>↩ Tool result · `toolu_01MgvQ9EHQr4ZcmpFjFtv2yj`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	
4	\usepackage{graphicx}
5	\usepackage{algorithm}
6	\usepackage{algorithmic}
7	
8	\usepackage{amsmath,amssymb,amsthm}
9	\usepackage{booktabs}
10	\usepackage{pifont}
11	\usepackage{multirow}
12	
13	\newtheorem{definition}{Definition}
14	\newtheorem{proposition}{Proposition}
15	\newtheorem{theorem}{Theorem}
16	\newtheorem{lemma}{Lemma}
17	\newtheorem{conjecture}{Conjecture}
18	\newtheorem{observation}{Observation}
19	\newtheorem{remark}{Remark}
20	
21	\setlength{\textfloatsep}{8pt plus 2pt minus 4pt}
22	\setlength{\dbltextfloatsep}{8pt plus 2pt minus 4pt}
23	\setlength{\floatsep}{8pt plus 2pt minus 4pt}
24	\setlength{\dblfloatsep}{8pt plus 2pt minus 4pt}
25	\graphicspath{{../../figures/paper/}}
26	
27	\title{Multi-Class Annotation Errors in Causal Inference:\\Topology-Dependent Bias, Sensitivity, and Correction}
28	
29	\author{Anonymous}
30	
31	\begin{document}
32	\maketitle
33	
34	\input{abstract}
35	
36	\input{introduction}
37	
38	\begin{figure*}[t]
39	\centering
40	\includegraphics[width=0.92\textwidth,height=0.18\textheight,keepaspectratio]{fig1_dag_taxonomy.pdf}
41	\vspace{-6pt}
42	\caption{Seven canonical DAG topologies with starred-node annotation~\cite{hernan_cole2009}. $A$ (latent) $\to$ $A^*$ (observed) via a dashed measurement edge; the causal role of $A$ varies: treatment (exposure), covariate (confounding, mediation, M-bias, front-door), selection (collider), instrument (IV).}
43	\label{fig:dag_taxonomy}
44	\end{figure*}
45	
46	\input{related_work}
47	
48	\input{method}
49	
50	\input{experiments}
51	
52	\input{conclusion}
53	
54	\bibliography{references}
55	
56	\appendix
57	\input{appendix_proofs}
58	
59	\end{document}
60	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1ea9522a-981e-4efa-a334-38de07bb9da0",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "610e244a-b40b-4954-a13a-ce3587e902ee",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\n\\usepackage{graphicx}\n\\usepackage{algorithm}\n\\usepackage{algorithmic}\n\n\\usepackage{amsmath,amssymb,amsthm}\n\\usepackage{booktabs}\n\\usepackage{pifont}\n\\usepackage{multirow}\n\n\\newtheorem{definition}{Definition}\n\\newtheorem{proposition}{Proposition}\n\\newtheorem{theorem}{Theorem}\n\\newtheorem{lemma}{Lemma}\n\\newtheorem{conjecture}{Conjecture}\n\\newtheorem{observation}{Observation}\n\\newtheorem{remark}{Remark}\n\n\\setlength{\\textfloatsep}{8pt plus 2pt minus 4pt}\n\\setlength{\\dbltextfloatsep}{8pt plus 2pt minus 4pt}\n\\setlength{\\floatsep}{8pt plus 2pt minus 4pt}\n\\setlength{\\dblfloatsep}{8pt plus 2pt minus 4pt}\n\\graphicspath{{../../figures/paper/}}\n\n\\title{Multi-Class Annotation Errors in Causal Inference:\\\\Topology-Dependent Bias, Sensitivity, and Correction}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.92\\textwidth,height=0.18\\textheight,keepaspectratio]{fig1_dag_taxonomy.pdf}\n\\vspace{-6pt}\n\\caption{Seven canonical DAG topologies with starred-node annotation~\\cite{hernan_cole2009}. $A$ (latent) $\\to$ $A^*$ (observed) via a dashed measurement edge; the causal role of $A$ varies: treatment (exposure), covariate (confounding, mediation, M-bias, front-door), selection (collider), instrument (IV).}\n\\label{fig:dag_taxonomy}\n\\end{figure*}\n\n\\input{related_work}\n\n\\input{method}\n\n\\input{experiments}\n\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{appendix_proofs}\n\n\\end{document}\n",
      "numLines": 60,
      "startLine": 1,
      "totalLines": 60
    }
  },
  "sourceToolAssistantUUID": "1ea9522a-981e-4efa-a334-38de07bb9da0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-24T06:35:33.551Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Se1xLjRskY3vRa3aqCe1rS`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/k3_symmetric_proof.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "610e244a-b40b-4954-a13a-ce3587e902ee",
  "isSidechain": false,
  "requestId": "req_011CbLvt7tPrBkeYFxVY9Aq8",
  "type": "assistant",
  "uuid": "8296c678-91f8-4b1f-b72c-6d1c8ce8b27f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018vXbX7pQCk9aC3VZYHVPNf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 327,
      "cache_read_input_tokens": 25522,
      "output_tokens": 667,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 327,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 667,
          "cache_read_input_tokens": 25522,
          "cache_creation_input_tokens": 327,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 327
          },
          "type": "message"
        }
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

_source line 30 · 2026-05-24T06:35:33.647Z_

```json
{
  "parentUuid": "93881f95-9c40-4e3e-b89b-02cbb8110d48",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "54befa2c-08e9-4ec6-8e61-1e3c5cf94293",
  "timestamp": "2026-05-24T06:35:33.647Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 31_

```json
{
  "type": "last-prompt",
  "leafUuid": "54befa2c-08e9-4ec6-8e61-1e3c5cf94293",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 32_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 33 · 2026-05-24T06:35:36.948Z_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read the appendix_proofs.tex file in chunks since it's too large. Let me also search for all `\textit` and `\emph` occurrences across all tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "54befa2c-08e9-4ec6-8e61-1e3c5cf94293",
  "isSidechain": false,
  "requestId": "req_011CbLvtc9kokrDmBWTTQS3L",
  "type": "assistant",
  "uuid": "bd3bffd6-3f52-4f4c-aca8-9c814a419151",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FVnv1xHA7QfFELUxtWKMx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17018,
      "cache_read_input_tokens": 25849,
      "output_tokens": 322,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17018,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 322,
          "cache_read_input_tokens": 25849,
          "cache_creation_input_tokens": 17018,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17018
          },
          "type": "message"
        }
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

_source line 34 · 2026-05-24T06:35:37.478Z_

Now let me search for all italic usage across the tex files and read the appendix in chunks.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bd3bffd6-3f52-4f4c-aca8-9c814a419151",
  "isSidechain": false,
  "requestId": "req_011CbLvtc9kokrDmBWTTQS3L",
  "type": "assistant",
  "uuid": "facc47e7-8464-4cf8-8a79-8e6f7d716e0b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FVnv1xHA7QfFELUxtWKMx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17018,
      "cache_read_input_tokens": 25849,
      "output_tokens": 322,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17018,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 322,
          "cache_read_input_tokens": 25849,
          "cache_creation_input_tokens": 17018,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17018
          },
          "type": "message"
        }
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

_source line 35 · 2026-05-24T06:35:40.311Z_

<details open><summary>🔧 Tool call — Grep · `toolu_018zMmC7bFgUagU8y1zM2Ux7`</summary>

```json
{
  "pattern": "\\\\textit\\{|\\\\emph\\{",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "facc47e7-8464-4cf8-8a79-8e6f7d716e0b",
  "isSidechain": false,
  "requestId": "req_011CbLvtc9kokrDmBWTTQS3L",
  "type": "assistant",
  "uuid": "9adbfcb4-f34c-46ac-9d0b-264e9bf8bcd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FVnv1xHA7QfFELUxtWKMx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17018,
      "cache_read_input_tokens": 25849,
      "output_tokens": 322,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17018,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 322,
          "cache_read_input_tokens": 25849,
          "cache_creation_input_tokens": 17018,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17018
          },
          "type": "message"
        }
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

_source line 36 · 2026-05-24T06:35:40.911Z_

<details><summary>↩ Tool result · `toolu_01QWVpx7qean4mgznWjeoDo8`</summary>

```text
1	\section{Proofs of Proposition~\ref{prop:signflip} and Theorem~\ref{thm:monotone}}
2	\label{app:proof}
3	
4	We provide algebraic proofs of sign preservation for the confounding and collider topologies (Proposition~\ref{prop:signflip}(a)--(b)), an explicit counterexample for exposure (Proposition~\ref{prop:signflip}(c)), numerical verification for mediation, M-bias, and front-door (Numerical Verification~1), and the monotonicity proof for confounding (Theorem~\ref{thm:monotone}).
5	Throughout, $A\in\{0,1,\dots,K{-}1\}$ with prior $p_k=P(A{=}k)$, and $C$ is a $K{\times}K$ column-stochastic confusion matrix with $C_{jk}=P(A^*{=}j\mid A{=}k)$.
6	We use category~0 as the reference and let $D_j=\mathbf{1}(A{=}j)$, $D_j^*=\mathbf{1}(A^*{=}j)$ for $j=1,\dots,K{-}1$.
7	
8	\subsection{Notation and Key Identities}
9	\label{app:notation}
10	
11	Under non-differential misclassification, the misclassified moments factor linearly through $C$.
12	Define the population vectors:
13	\begin{align}
14	  q_j &= P(A^*{=}j) = \textstyle\sum_k C_{jk}\,p_k, \label{eq:q}\\
15	  \mathrm{ct}_j &= \mathbb{E}[T\cdot D_j^*] = \textstyle\sum_k C_{jk}\,\mathbb{E}[T\cdot D_k], \label{eq:ct}\\
16	  \mathrm{cy}_j &= \mathbb{E}[Y\cdot D_j^*] = \textstyle\sum_k C_{jk}\,\mathbb{E}[Y\cdot D_k]. \label{eq:cy}
17	\end{align}
18	Write $q = Cp$, $\mathrm{ct} = C\,\mathbb{E}[T\cdot D]$, and $\mathrm{cy} = C\,\mathbb{E}[Y\cdot D]$, where $D=(D_0,\dots,D_{K-1})^\top$.
19	
20	\subsection{Frisch--Waugh--Lovell Decomposition}
21	\label{app:fwl}
22	
23	For topologies where $T$ is directly observed (confounding, mediation, collider, M-bias, front-door), the estimator regresses $Y$ on $Z^*=(1,T,D_1^*,\dots,D_{K-1}^*)$.
24	By the Frisch--Waugh--Lovell (FWL) theorem, the coefficient on $T$ satisfies:
25	\begin{equation}
26	  \operatorname{plim}\hat{\tau}(C)
27	  = \frac{\mathbb{E}[\tilde{T}\,\tilde{Y}]}{\mathbb{E}[\tilde{T}^2]},
28	  \label{eq:fwl}
29	\end{equation}
30	where $\tilde{T}=T-\mathbb{E}[T\mid A^*]$ and $\tilde{Y}=Y-\mathbb{E}[Y\mid A^*]$ are residuals from projecting onto $(1,D_1^*,\dots,D_{K-1}^*)$.
31	
32	\begin{lemma}[Bias decomposition]
33	\label{lem:bias_decomp}
34	Suppose $Y = \tau T + f(A) + \varepsilon_Y$ with $\varepsilon_Y \perp (T, A, A^*)$.
35	Then
36	\begin{equation}
37	  \operatorname{plim}\hat\tau(C) = \tau + \frac{R(C)}{D(C)},
38	  \label{eq:bias_decomp}
39	\end{equation}
40	where
41	\begin{align}
42	  R(C) &= \mathbb{E}\bigl[\operatorname{Cov}(T,\,f(A)\mid A^*)\bigr], \label{eq:R}\\
43	  D(C) &= \mathbb{E}\bigl[\operatorname{Var}(T\mid A^*)\bigr] > 0. \label{eq:D}
44	\end{align}
45	\end{lemma}
46	
47	\begin{proof}
48	Expand $\tilde{Y}$ using $Y=\tau T + f(A) + \varepsilon_Y$:
49	\[
50	  \tilde{Y} = \tau\,\tilde{T} + \bigl(f(A) - \mathbb{E}[f(A)\mid A^*]\bigr) + \varepsilon_Y.
51	\]
52	Since $\tilde{T}$ is measurable w.r.t.\ $(T,A^*)$ and $\varepsilon_Y\perp(T,A,A^*)$:
53	\[
54	  \mathbb{E}[\tilde{T}\,\tilde{Y}]
55	  = \tau\,\mathbb{E}[\tilde{T}^2]
56	  + \mathbb{E}\bigl[\tilde{T}\,\bigl(f(A)-\mathbb{E}[f(A)\mid A^*]\bigr)\bigr].
57	\]
58	The numerator residual is $R(C) = \mathbb{E}[\tilde{T}(f(A)-\mathbb{E}[f(A)\mid A^*])]$, and the denominator is $D(C) = \mathbb{E}[\tilde{T}^2]$.
59	
60	By the law of total covariance:
61	\[
62	  R(C) = \sum_{j=0}^{K-1} q_j\,\operatorname{Cov}(T,\,f(A)\mid A^*{=}j)
63	  = \mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)].
64	\]
65	For $D(C)>0$: decompose $T = g(A) + \varepsilon_T$ where $g(A)=\mathbb{E}[T\mid A]$ (for confounding) or simply note that $T$ has exogenous variation independent of $A^*$ (for mediation).
66	In both cases, $\tilde{T}=\bigl(g(A)-\mathbb{E}[g(A)\mid A^*]\bigr)+\varepsilon_T'$, where $\varepsilon_T'$ is the component of $T$ independent of $(A,A^*)$.
67	Hence $D(C)\geq\operatorname{Var}(\varepsilon_T')>0$.
68	\end{proof}
69	
70	\subsection{Confounding Topology ($A$ = Confounder)}
71	\label{app:confounding}
72	
73	\paragraph{Data-generating process.}
74	$A\to T$, $A\to Y$, $T\to Y$.
75	Using dummy coding with category 0 as reference:
76	\begin{align*}
77	  T &= \sum_{j=1}^{K-1}\alpha_j D_j + \varepsilon_T,\quad
78	  \varepsilon_T\sim\mathcal{N}(0,\sigma_T^2),\;\varepsilon_T\perp A,\\
79	  Y &= \tau\, T + \sum_{j=1}^{K-1}\beta_j^{(A)} D_j + \varepsilon_Y,\quad
80	  \varepsilon_Y\sim\mathcal{N}(0,1),\;\varepsilon_Y\perp(T,A).
81	\end{align*}
82	Define $g(k)=\sum_{j}\alpha_j\mathbf{1}(k{=}j)$ and $f(k)=\sum_{j}\beta_j^{(A)}\mathbf{1}(k{=}j)$, so $g(0)=f(0)=0$.
83	
84	\paragraph{Closed-form plim.}
85	Using the FWL decomposition, the coefficient on $T$ is:
86	\begin{equation}
87	  \operatorname{plim}\hat\tau(C)
88	  = \frac{\mu_{TY} - \sum_{j=0}^{K-1}\frac{\mathrm{ct}_j\,\mathrm{cy}_j}{q_j}}
89	  {s_T - \sum_{j=0}^{K-1}\frac{\mathrm{ct}_j^2}{q_j}},
90	  \label{eq:plim_conf}
91	\end{equation}
92	where $s_T=\mathbb{E}[T^2]$, $\mu_{TY}=\mathbb{E}[TY]$, and $\mathrm{ct}_j$, $\mathrm{cy}_j$, $q_j$ are defined in~\eqref{eq:q}--\eqref{eq:cy}.
93	
94	\begin{proof}[Derivation]
95	By FWL, $\operatorname{plim}\hat\tau = \mathbb{E}[\tilde{T}Y]/\mathbb{E}[\tilde{T}^2]$ where $\tilde{T}=T-\mathbb{E}[T\mid A^*]$.
96	Since $\mathbb{E}[T\mid A^*{=}j]=\mathrm{ct}_j/q_j$:
97	\begin{align*}
98	  \mathbb{E}[\tilde{T}^2]
99	  &= \mathbb{E}[T^2] - \sum_j q_j\bigl(\mathrm{ct}_j/q_j\bigr)^2
100	  = s_T - \sum_j \mathrm{ct}_j^2/q_j,\\
101	  \mathbb{E}[\tilde{T}\,Y]
102	  &= \mathbb{E}[TY] - \sum_j \bigl(\mathrm{ct}_j/q_j\bigr)\,\mathbb{E}[Y\cdot D_j^*]
103	  = \mu_{TY} - \sum_j \mathrm{ct}_j\,\mathrm{cy}_j/q_j.
104	\end{align*}
105	\end{proof}
106	
107	\paragraph{Verification at $C=I$.}
108	When $C=I$: $q_j=p_j$, $\mathrm{ct}_j=\mathbb{E}[T D_j]=\alpha_j p_j$, $\mathrm{cy}_j=\mathbb{E}[Y D_j]=p_j(\tau\alpha_j+\beta_j^{(A)})$.
109	Direct substitution yields numerator $= \tau\sigma_T^2$ and denominator $= \sigma_T^2$, giving $\operatorname{plim}\hat\tau = \tau$.
110	
111	\paragraph{Bias structure.}
112	By Lemma~\ref{lem:bias_decomp}:
113	\begin{equation}
114	  \operatorname{plim}\hat\tau(C) = \tau + B(C),\quad
115	  B(C) = \frac{\mathbb{E}[\operatorname{Cov}(g(A),\,f(A)\mid A^*)]}{D(C)}.
116	  \label{eq:bias_conf}
117	\end{equation}
118	By the law of total covariance:
119	\begin{equation}
120	  \mathbb{E}[\operatorname{Cov}(g,f\mid A^*)]
121	  = \operatorname{Cov}(g(A),f(A))
122	  - \operatorname{Cov}\bigl(\mathbb{E}[g(A)\mid A^*],\;\mathbb{E}[f(A)\mid A^*]\bigr).
123	  \label{eq:lotc}
124	\end{equation}
125	
126	At $C=I$: $\mathbb{E}[g\mid A^*]=g(A)$, so the between-group covariance equals $\operatorname{Cov}(g,f)$ and $B(I)=0$.
127	
128	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ (uniform, $A^*\perp A$): $\mathbb{E}[g\mid A^*]$ is constant, so the between-group covariance is zero and
129	\begin{equation}
130	  B_{\mathrm{OV}} \;\equiv\; B\bigl(\tfrac{1}{K}\mathbf{1}\mathbf{1}^\top\bigr)
131	  = \frac{\operatorname{Cov}(g(A),\,f(A))}{\operatorname{Var}(T)},
132	  \label{eq:bov}
133	\end{equation}
134	which equals the classical omitted-variable bias (no control for $A$).
135	
136	\paragraph{Sign preservation condition.}
137	Since $D(C)>0$, sign$(\operatorname{plim}\hat\tau) = $ sign$(\tau\cdot D(C) + R(C))$.
138	For sign preservation, it suffices that $R(C)$ does not overwhelm $\tau\cdot D(C)$.
139	
140	\begin{proposition}[Confounding sign preservation --- proportional case]
141	\label{prop:conf_prop}
142	If $f(A) = \lambda\,g(A)$ for some constant $\lambda$ (i.e., the confounder effects on $T$ and $Y$ are proportional), then
143	\begin{equation}
144	  B(C) = \bigl(1-\xi(C)\bigr)\,B_{\mathrm{OV}},
145	  \label{eq:convex}
146	\end{equation}
147	where
148	\[
149	  \xi(C) = \frac{\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])\;\sigma_T^2}
150	  {\operatorname{Var}(g(A))\bigl(\operatorname{Var}(g(A))-\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])+\sigma_T^2\bigr)}
151	  \;\in\;[0,1].
152	\]
153	Consequently, $B(C)$ lies between $0$ and $B_{\mathrm{OV}}$, and $\operatorname{sign}(\operatorname{plim}\hat\tau)=\operatorname{sign}(\tau)$ whenever $\operatorname{sign}(\tau)=\operatorname{sign}(\tau+B_{\mathrm{OV}})$.
154	\end{proposition}
155	
156	\begin{proof}
157	When $f=\lambda g$: the between-group covariance in~\eqref{eq:lotc} becomes $\lambda\,\operatorname{Var}(\mathbb{E}[g\mid A^*])$, and $\operatorname{Cov}(g,f)=\lambda\,\operatorname{Var}(g)$.
158	So $R(C)=\lambda\bigl(\operatorname{Var}(g)-\operatorname{Var}(\mathbb{E}[g\mid A^*])\bigr)=\lambda\,V_W$, where $V_W=\operatorname{Var}(g)-V_B$ with $V_B=\operatorname{Var}(\mathbb{E}[g\mid A^*])$.
159	Similarly, $D(C)=V_W+\sigma_T^2$.
160	Hence
161	\[
162	  B(C) = \frac{\lambda\,V_W}{V_W+\sigma_T^2},\qquad
163	  B_{\mathrm{OV}} = \frac{\lambda\,V}{V+\sigma_T^2},
164	\]
165	where $V=\operatorname{Var}(g)=V_B+V_W$.
166	The ratio
167	\[
168	  \frac{B(C)}{B_{\mathrm{OV}}} = \frac{V_W(V+\sigma_T^2)}{V(V_W+\sigma_T^2)} = 1 - \xi(C)
169	\]
170	is a decreasing function of $V_B\in[0,V]$.
171	At $V_B=0$ (no classification, $C$ uniform): $\xi=0$, $B=B_{\mathrm{OV}}$.
172	At $V_B=V$ (perfect classification, $C=I$): $\xi=1$, $B=0$.
173	Since $0\leq V_B\leq V$, we have $\xi\in[0,1]$ and $B(C)\in[0,B_{\mathrm{OV}}]$ (with the sign of $B_{\mathrm{OV}}$).
174	\end{proof}
175	
176	\begin{proposition}[Confounding sign preservation --- general case]
177	\label{prop:conf_gen}
178	For general $g$ and $f$ (not necessarily proportional), define the worst-case bias bound
179	\begin{equation}
180	  \bar{B} \;=\; \frac{\sqrt{\operatorname{Var}(g(A))\,\operatorname{Var}(f(A))}}{\sigma_T^2}.
181	  \label{eq:bbar}
182	\end{equation}
183	If $|\tau| > \bar{B}$, then $\operatorname{sign}(\operatorname{plim}\hat\tau(C))=\operatorname{sign}(\tau)$ for \emph{all} column-stochastic $C$.
184	\end{proposition}
185	
186	\begin{proof}
187	We need $\operatorname{sign}(\tau\cdot D(C)+R(C))=\operatorname{sign}(\tau)$, which holds if $|R(C)|<|\tau|\cdot D(C)$.
188	Since $D(C)\geq\sigma_T^2$ (shown in Lemma~\ref{lem:bias_decomp}), it suffices to show $|R(C)|<|\tau|\,\sigma_T^2$.
189	
190	\emph{Step 1: Bound $|R(C)|$.}
191	$R(C)=\mathbb{E}[\operatorname{Cov}(g(A),f(A)\mid A^*)]$.
192	By the Cauchy--Schwarz inequality applied to each within-group covariance:
193	\[
194	  |\operatorname{Cov}(g,f\mid A^*{=}j)|
195	  \leq \sqrt{\operatorname{Var}(g\mid A^*{=}j)\,\operatorname{Var}(f\mid A^*{=}j)}.
196	\]
197	Taking expectations and applying Cauchy--Schwarz again:
198	\begin{align*}
199	  |R(C)|
200	  &\leq \mathbb{E}\bigl[\sqrt{\operatorname{Var}(g\mid A^*)\,\operatorname{Var}(f\mid A^*)}\bigr]\\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "59111cf5-62e0-47a3-bd35-1565c654d3c2",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "ca235f53-8a6b-42d8-99d6-68e01cfb7585",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\section{Proofs of Proposition~\\ref{prop:signflip} and Theorem~\\ref{thm:monotone}}\n\\label{app:proof}\n\nWe provide algebraic proofs of sign preservation for the confounding and collider topologies (Proposition~\\ref{prop:signflip}(a)--(b)), an explicit counterexample for exposure (Proposition~\\ref{prop:signflip}(c)), numerical verification for mediation, M-bias, and front-door (Numerical Verification~1), and the monotonicity proof for confounding (Theorem~\\ref{thm:monotone}).\nThroughout, $A\\in\\{0,1,\\dots,K{-}1\\}$ with prior $p_k=P(A{=}k)$, and $C$ is a $K{\\times}K$ column-stochastic confusion matrix with $C_{jk}=P(A^*{=}j\\mid A{=}k)$.\nWe use category~0 as the reference and let $D_j=\\mathbf{1}(A{=}j)$, $D_j^*=\\mathbf{1}(A^*{=}j)$ for $j=1,\\dots,K{-}1$.\n\n\\subsection{Notation and Key Identities}\n\\label{app:notation}\n\nUnder non-differential misclassification, the misclassified moments factor linearly through $C$.\nDefine the population vectors:\n\\begin{align}\n  q_j &= P(A^*{=}j) = \\textstyle\\sum_k C_{jk}\\,p_k, \\label{eq:q}\\\\\n  \\mathrm{ct}_j &= \\mathbb{E}[T\\cdot D_j^*] = \\textstyle\\sum_k C_{jk}\\,\\mathbb{E}[T\\cdot D_k], \\label{eq:ct}\\\\\n  \\mathrm{cy}_j &= \\mathbb{E}[Y\\cdot D_j^*] = \\textstyle\\sum_k C_{jk}\\,\\mathbb{E}[Y\\cdot D_k]. \\label{eq:cy}\n\\end{align}\nWrite $q = Cp$, $\\mathrm{ct} = C\\,\\mathbb{E}[T\\cdot D]$, and $\\mathrm{cy} = C\\,\\mathbb{E}[Y\\cdot D]$, where $D=(D_0,\\dots,D_{K-1})^\\top$.\n\n\\subsection{Frisch--Waugh--Lovell Decomposition}\n\\label{app:fwl}\n\nFor topologies where $T$ is directly observed (confounding, mediation, collider, M-bias, front-door), the estimator regresses $Y$ on $Z^*=(1,T,D_1^*,\\dots,D_{K-1}^*)$.\nBy the Frisch--Waugh--Lovell (FWL) theorem, the coefficient on $T$ satisfies:\n\\begin{equation}\n  \\operatorname{plim}\\hat{\\tau}(C)\n  = \\frac{\\mathbb{E}[\\tilde{T}\\,\\tilde{Y}]}{\\mathbb{E}[\\tilde{T}^2]},\n  \\label{eq:fwl}\n\\end{equation}\nwhere $\\tilde{T}=T-\\mathbb{E}[T\\mid A^*]$ and $\\tilde{Y}=Y-\\mathbb{E}[Y\\mid A^*]$ are residuals from projecting onto $(1,D_1^*,\\dots,D_{K-1}^*)$.\n\n\\begin{lemma}[Bias decomposition]\n\\label{lem:bias_decomp}\nSuppose $Y = \\tau T + f(A) + \\varepsilon_Y$ with $\\varepsilon_Y \\perp (T, A, A^*)$.\nThen\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C) = \\tau + \\frac{R(C)}{D(C)},\n  \\label{eq:bias_decomp}\n\\end{equation}\nwhere\n\\begin{align}\n  R(C) &= \\mathbb{E}\\bigl[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)\\bigr], \\label{eq:R}\\\\\n  D(C) &= \\mathbb{E}\\bigl[\\operatorname{Var}(T\\mid A^*)\\bigr] > 0. \\label{eq:D}\n\\end{align}\n\\end{lemma}\n\n\\begin{proof}\nExpand $\\tilde{Y}$ using $Y=\\tau T + f(A) + \\varepsilon_Y$:\n\\[\n  \\tilde{Y} = \\tau\\,\\tilde{T} + \\bigl(f(A) - \\mathbb{E}[f(A)\\mid A^*]\\bigr) + \\varepsilon_Y.\n\\]\nSince $\\tilde{T}$ is measurable w.r.t.\\ $(T,A^*)$ and $\\varepsilon_Y\\perp(T,A,A^*)$:\n\\[\n  \\mathbb{E}[\\tilde{T}\\,\\tilde{Y}]\n  = \\tau\\,\\mathbb{E}[\\tilde{T}^2]\n  + \\mathbb{E}\\bigl[\\tilde{T}\\,\\bigl(f(A)-\\mathbb{E}[f(A)\\mid A^*]\\bigr)\\bigr].\n\\]\nThe numerator residual is $R(C) = \\mathbb{E}[\\tilde{T}(f(A)-\\mathbb{E}[f(A)\\mid A^*])]$, and the denominator is $D(C) = \\mathbb{E}[\\tilde{T}^2]$.\n\nBy the law of total covariance:\n\\[\n  R(C) = \\sum_{j=0}^{K-1} q_j\\,\\operatorname{Cov}(T,\\,f(A)\\mid A^*{=}j)\n  = \\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)].\n\\]\nFor $D(C)>0$: decompose $T = g(A) + \\varepsilon_T$ where $g(A)=\\mathbb{E}[T\\mid A]$ (for confounding) or simply note that $T$ has exogenous variation independent of $A^*$ (for mediation).\nIn both cases, $\\tilde{T}=\\bigl(g(A)-\\mathbb{E}[g(A)\\mid A^*]\\bigr)+\\varepsilon_T'$, where $\\varepsilon_T'$ is the component of $T$ independent of $(A,A^*)$.\nHence $D(C)\\geq\\operatorname{Var}(\\varepsilon_T')>0$.\n\\end{proof}\n\n\\subsection{Confounding Topology ($A$ = Confounder)}\n\\label{app:confounding}\n\n\\paragraph{Data-generating process.}\n$A\\to T$, $A\\to Y$, $T\\to Y$.\nUsing dummy coding with category 0 as reference:\n\\begin{align*}\n  T &= \\sum_{j=1}^{K-1}\\alpha_j D_j + \\varepsilon_T,\\quad\n  \\varepsilon_T\\sim\\mathcal{N}(0,\\sigma_T^2),\\;\\varepsilon_T\\perp A,\\\\\n  Y &= \\tau\\, T + \\sum_{j=1}^{K-1}\\beta_j^{(A)} D_j + \\varepsilon_Y,\\quad\n  \\varepsilon_Y\\sim\\mathcal{N}(0,1),\\;\\varepsilon_Y\\perp(T,A).\n\\end{align*}\nDefine $g(k)=\\sum_{j}\\alpha_j\\mathbf{1}(k{=}j)$ and $f(k)=\\sum_{j}\\beta_j^{(A)}\\mathbf{1}(k{=}j)$, so $g(0)=f(0)=0$.\n\n\\paragraph{Closed-form plim.}\nUsing the FWL decomposition, the coefficient on $T$ is:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C)\n  = \\frac{\\mu_{TY} - \\sum_{j=0}^{K-1}\\frac{\\mathrm{ct}_j\\,\\mathrm{cy}_j}{q_j}}\n  {s_T - \\sum_{j=0}^{K-1}\\frac{\\mathrm{ct}_j^2}{q_j}},\n  \\label{eq:plim_conf}\n\\end{equation}\nwhere $s_T=\\mathbb{E}[T^2]$, $\\mu_{TY}=\\mathbb{E}[TY]$, and $\\mathrm{ct}_j$, $\\mathrm{cy}_j$, $q_j$ are defined in~\\eqref{eq:q}--\\eqref{eq:cy}.\n\n\\begin{proof}[Derivation]\nBy FWL, $\\operatorname{plim}\\hat\\tau = \\mathbb{E}[\\tilde{T}Y]/\\mathbb{E}[\\tilde{T}^2]$ where $\\tilde{T}=T-\\mathbb{E}[T\\mid A^*]$.\nSince $\\mathbb{E}[T\\mid A^*{=}j]=\\mathrm{ct}_j/q_j$:\n\\begin{align*}\n  \\mathbb{E}[\\tilde{T}^2]\n  &= \\mathbb{E}[T^2] - \\sum_j q_j\\bigl(\\mathrm{ct}_j/q_j\\bigr)^2\n  = s_T - \\sum_j \\mathrm{ct}_j^2/q_j,\\\\\n  \\mathbb{E}[\\tilde{T}\\,Y]\n  &= \\mathbb{E}[TY] - \\sum_j \\bigl(\\mathrm{ct}_j/q_j\\bigr)\\,\\mathbb{E}[Y\\cdot D_j^*]\n  = \\mu_{TY} - \\sum_j \\mathrm{ct}_j\\,\\mathrm{cy}_j/q_j.\n\\end{align*}\n\\end{proof}\n\n\\paragraph{Verification at $C=I$.}\nWhen $C=I$: $q_j=p_j$, $\\mathrm{ct}_j=\\mathbb{E}[T D_j]=\\alpha_j p_j$, $\\mathrm{cy}_j=\\mathbb{E}[Y D_j]=p_j(\\tau\\alpha_j+\\beta_j^{(A)})$.\nDirect substitution yields numerator $= \\tau\\sigma_T^2$ and denominator $= \\sigma_T^2$, giving $\\operatorname{plim}\\hat\\tau = \\tau$.\n\n\\paragraph{Bias structure.}\nBy Lemma~\\ref{lem:bias_decomp}:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C) = \\tau + B(C),\\quad\n  B(C) = \\frac{\\mathbb{E}[\\operatorname{Cov}(g(A),\\,f(A)\\mid A^*)]}{D(C)}.\n  \\label{eq:bias_conf}\n\\end{equation}\nBy the law of total covariance:\n\\begin{equation}\n  \\mathbb{E}[\\operatorname{Cov}(g,f\\mid A^*)]\n  = \\operatorname{Cov}(g(A),f(A))\n  - \\operatorname{Cov}\\bigl(\\mathbb{E}[g(A)\\mid A^*],\\;\\mathbb{E}[f(A)\\mid A^*]\\bigr).\n  \\label{eq:lotc}\n\\end{equation}\n\nAt $C=I$: $\\mathbb{E}[g\\mid A^*]=g(A)$, so the between-group covariance equals $\\operatorname{Cov}(g,f)$ and $B(I)=0$.\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ (uniform, $A^*\\perp A$): $\\mathbb{E}[g\\mid A^*]$ is constant, so the between-group covariance is zero and\n\\begin{equation}\n  B_{\\mathrm{OV}} \\;\\equiv\\; B\\bigl(\\tfrac{1}{K}\\mathbf{1}\\mathbf{1}^\\top\\bigr)\n  = \\frac{\\operatorname{Cov}(g(A),\\,f(A))}{\\operatorname{Var}(T)},\n  \\label{eq:bov}\n\\end{equation}\nwhich equals the classical omitted-variable bias (no control for $A$).\n\n\\paragraph{Sign preservation condition.}\nSince $D(C)>0$, sign$(\\operatorname{plim}\\hat\\tau) = $ sign$(\\tau\\cdot D(C) + R(C))$.\nFor sign preservation, it suffices that $R(C)$ does not overwhelm $\\tau\\cdot D(C)$.\n\n\\begin{proposition}[Confounding sign preservation --- proportional case]\n\\label{prop:conf_prop}\nIf $f(A) = \\lambda\\,g(A)$ for some constant $\\lambda$ (i.e., the confounder effects on $T$ and $Y$ are proportional), then\n\\begin{equation}\n  B(C) = \\bigl(1-\\xi(C)\\bigr)\\,B_{\\mathrm{OV}},\n  \\label{eq:convex}\n\\end{equation}\nwhere\n\\[\n  \\xi(C) = \\frac{\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])\\;\\sigma_T^2}\n  {\\operatorname{Var}(g(A))\\bigl(\\operatorname{Var}(g(A))-\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])+\\sigma_T^2\\bigr)}\n  \\;\\in\\;[0,1].\n\\]\nConsequently, $B(C)$ lies between $0$ and $B_{\\mathrm{OV}}$, and $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau)=\\operatorname{sign}(\\tau)$ whenever $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau+B_{\\mathrm{OV}})$.\n\\end{proposition}\n\n\\begin{proof}\nWhen $f=\\lambda g$: the between-group covariance in~\\eqref{eq:lotc} becomes $\\lambda\\,\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])$, and $\\operatorname{Cov}(g,f)=\\lambda\\,\\operatorname{Var}(g)$.\nSo $R(C)=\\lambda\\bigl(\\operatorname{Var}(g)-\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])\\bigr)=\\lambda\\,V_W$, where $V_W=\\operatorname{Var}(g)-V_B$ with $V_B=\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])$.\nSimilarly, $D(C)=V_W+\\sigma_T^2$.\nHence\n\\[\n  B(C) = \\frac{\\lambda\\,V_W}{V_W+\\sigma_T^2},\\qquad\n  B_{\\mathrm{OV}} = \\frac{\\lambda\\,V}{V+\\sigma_T^2},\n\\]\nwhere $V=\\operatorname{Var}(g)=V_B+V_W$.\nThe ratio\n\\[\n  \\frac{B(C)}{B_{\\mathrm{OV}}} = \\frac{V_W(V+\\sigma_T^2)}{V(V_W+\\sigma_T^2)} = 1 - \\xi(C)\n\\]\nis a decreasing function of $V_B\\in[0,V]$.\nAt $V_B=0$ (no classification, $C$ uniform): $\\xi=0$, $B=B_{\\mathrm{OV}}$.\nAt $V_B=V$ (perfect classification, $C=I$): $\\xi=1$, $B=0$.\nSince $0\\leq V_B\\leq V$, we have $\\xi\\in[0,1]$ and $B(C)\\in[0,B_{\\mathrm{OV}}]$ (with the sign of $B_{\\mathrm{OV}}$).\n\\end{proof}\n\n\\begin{proposition}[Confounding sign preservation --- general case]\n\\label{prop:conf_gen}\nFor general $g$ and $f$ (not necessarily proportional), define the worst-case bias bound\n\\begin{equation}\n  \\bar{B} \\;=\\; \\frac{\\sqrt{\\operatorname{Var}(g(A))\\,\\operatorname{Var}(f(A))}}{\\sigma_T^2}.\n  \\label{eq:bbar}\n\\end{equation}\nIf $|\\tau| > \\bar{B}$, then $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau(C))=\\operatorname{sign}(\\tau)$ for \\emph{all} column-stochastic $C$.\n\\end{proposition}\n\n\\begin{proof}\nWe need $\\operatorname{sign}(\\tau\\cdot D(C)+R(C))=\\operatorname{sign}(\\tau)$, which holds if $|R(C)|<|\\tau|\\cdot D(C)$.\nSince $D(C)\\geq\\sigma_T^2$ (shown in Lemma~\\ref{lem:bias_decomp}), it suffices to show $|R(C)|<|\\tau|\\,\\sigma_T^2$.\n\n\\emph{Step 1: Bound $|R(C)|$.}\n$R(C)=\\mathbb{E}[\\operatorname{Cov}(g(A),f(A)\\mid A^*)]$.\nBy the Cauchy--Schwarz inequality applied to each within-group covariance:\n\\[\n  |\\operatorname{Cov}(g,f\\mid A^*{=}j)|\n  \\leq \\sqrt{\\operatorname{Var}(g\\mid A^*{=}j)\\,\\operatorname{Var}(f\\mid A^*{=}j)}.\n\\]\nTaking expectations and applying Cauchy--Schwarz again:\n\\begin{align*}\n  |R(C)|\n  &\\leq \\mathbb{E}\\bigl[\\sqrt{\\operatorname{Var}(g\\mid A^*)\\,\\operatorname{Var}(f\\mid A^*)}\\bigr]\\\\",
      "numLines": 200,
      "startLine": 1,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "59111cf5-62e0-47a3-bd35-1565c654d3c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 37 · 2026-05-24T06:35:40.332Z_

<details><summary>↩ Tool result · `toolu_018zMmC7bFgUagU8y1zM2Ux7`</summary>

```text
docs/paper/related_work.tex:5:[Omitted long matching line]
docs/paper/main.bbl:7:\newblock In \emph{Proceedings of the International AAAI Conference on Web and
docs/paper/main.bbl:16:\newblock \emph{Science}, 382(6671):669--674.
docs/paper/main.bbl:23:\newblock \emph{Journal of the American Statistical Association},
docs/paper/main.bbl:31:\newblock In \emph{Proceedings of the 2025 Conference on Empirical Methods in
docs/paper/main.bbl:40:\newblock \emph{arXiv preprint arXiv:2509.08825}.
docs/paper/main.bbl:48:\newblock \emph{Oxford Bulletin of Economics and Statistics}, 86(4):951--993.
docs/paper/main.bbl:55:\newblock \emph{Sociological Methods \& Research}, 46(3):303--341.
docs/paper/main.bbl:61:\newblock In James~J. Heckman and Edward~E. Leamer, editors, \emph{Handbook of
docs/paper/main.bbl:68:\newblock \emph{Journal of Clinical Epidemiology}, 46(1):57--63.
docs/paper/main.bbl:74:\newblock \emph{Biometrics}, 10(4):478--486.
docs/paper/main.bbl:78:\newblock \emph{Measurement Error: Models, Methods, and Applications}.
docs/paper/main.bbl:86:\newblock \emph{arXiv preprint arXiv:2502.06343}.
docs/paper/main.bbl:95:\newblock \emph{arXiv preprint arXiv:2601.02370}.
docs/paper/main.bbl:101:\newblock \emph{Measurement Error in Nonlinear Models: A Modern Perspective},
docs/paper/main.bbl:109:\newblock \emph{arXiv preprint arXiv:2412.14461}.
docs/paper/main.bbl:115:\newblock \emph{Journal of the Royal Statistical Society: Series B (Statistical
docs/paper/main.bbl:122:\newblock In \emph{Proceedings of the 41st International Conference on Machine
docs/paper/main.bbl:123:  Learning}, volume 235 of \emph{Proceedings of Machine Learning Research},
docs/paper/main.bbl:130:\newblock \emph{Epidemiology}, 27(3):368--377.
docs/paper/main.bbl:137:\newblock \emph{American Journal of Epidemiology}, 132(4):746--748.
docs/paper/main.bbl:145:\newblock \emph{Annals of Epidemiology}, 58:104--123.
docs/paper/main.bbl:152:\newblock In \emph{Advances in Neural Information Processing Systems 36}.
docs/paper/main.bbl:163:\newblock \emph{Transactions of the Association for Computational Linguistics},
docs/paper/main.bbl:169:\newblock \emph{Econometrica}, 1(4):387--401.
docs/paper/main.bbl:176:\newblock \emph{Proceedings of the National Academy of Sciences},
docs/paper/main.bbl:184:\newblock In \emph{Proceedings of the 2025 Conference of the North American
docs/paper/main.bbl:192:\newblock \emph{Epidemiology}, 14:300--306.
docs/paper/main.bbl:196:\newblock \emph{Text as Data: A New Framework for Machine Learning and the
docs/paper/main.bbl:202:\newblock \emph{Measurement Error and Misclassification in Statistics and
docs/paper/main.bbl:210:\newblock \emph{American Journal of Epidemiology}, 170(8):959--962.
docs/paper/main.bbl:214:\newblock \emph{Causal Inference: What If}.
docs/paper/main.bbl:222:\newblock \emph{Journal of Econometrics}, 144(1):27--61.
docs/paper/main.bbl:228:\newblock \emph{Statistical Science}, 25(1):51--71.
docs/paper/main.bbl:234:\newblock \emph{American Journal of Political Science}, 54(2):543--560.
docs/paper/main.bbl:241:\newblock \emph{International Journal of Epidemiology}, 34(3):680--687.
docs/paper/main.bbl:249:\newblock In \emph{Proceedings of the 58th Annual Meeting of the Association
docs/paper/main.bbl:255:\newblock In \emph{Proceedings of the 42nd International Conference on Machine
docs/paper/main.bbl:263:\newblock \emph{Biometrics}, 62(1):85--96.
docs/paper/main.bbl:269:\newblock \emph{Biometrika}, 101(2):423--437.
docs/paper/main.bbl:273:\newblock \href {https://doi.org/10.1007/978-0-387-87959-8} {\emph{Applying
docs/paper/main.bbl:281:\newblock In \emph{AIM-FM Workshop, NeurIPS 2024}.
docs/paper/main.bbl:288:\newblock \emph{Journal of the American Statistical Association},
docs/paper/main.bbl:295:\newblock \emph{Econometrica}, 74(3):631--665.
docs/paper/main.bbl:302:\newblock \emph{Epidemiology}, 29(5):e45--e47.
docs/paper/main.bbl:308:\newblock \emph{arXiv preprint arXiv:2604.11581}.
docs/paper/main.bbl:314:\newblock \emph{Journal of Econometrics}, 208(2):487--506.
docs/paper/main.bbl:320:\newblock \emph{Epidemiology}, 23(3):433--439.
docs/paper/main.bbl:326:\newblock \emph{Journal of Business \& Economic Statistics}, 37(2):187--204.
docs/paper/main.bbl:332:\newblock \emph{arXiv preprint arXiv:2306.00176}.
docs/paper/main.bbl:336:\newblock \emph{Causality: Models, Reasoning and Inference}, 2nd edition.
docs/paper/main.bbl:345:\newblock In \emph{Proceedings of the 2021 Conference of the North American
docs/paper/main.bbl:353:  Rosa~L. Matzkin, editors, \emph{Handbook of Econometrics}, volume~7A, pages
docs/paper/main.bbl:360:\newblock \emph{Statistical Methods in Medical Research}, 28(7):2049--2068.
docs/paper/main.bbl:366:\newblock \emph{Statistics in Medicine}, 38(10):1835--1854.
docs/paper/main.bbl:372:\newblock \emph{The Annals of Statistics}, 13(4):1335--1351.
docs/paper/main.bbl:379:\newblock In \emph{Proceedings of the 2024 Conference on Empirical Methods in
docs/paper/main.bbl:388:\newblock \emph{Communication Methods and Measures}, 18(3):278--299.
docs/paper/main.bbl:395:\newblock \emph{Psychological Methods}, 18(2):137--150.
docs/paper/main.bbl:399:\newblock \emph{Explanation in Causal Inference: Methods for Mediation and
docs/paper/main.bbl:407:\newblock \emph{Annals of Internal Medicine}, 167:268--274.
docs/paper/main.bbl:413:\newblock \emph{Statistics in Medicine}, 20(5):771--784.
docs/paper/main.bbl:419:\newblock \emph{Statistical Methods in Medical Research}.
docs/paper/main.bbl:426:\newblock In \emph{Proceedings of the 2018 Conference on Empirical Methods in
docs/paper/main.bbl:435:\newblock \emph{Computational Linguistics}, 50(1):237--291.
docs/paper/main.bbl:441:\newblock \emph{Proceedings of the National Academy of Sciences}.
docs/paper/acl_natbib.bst:378:    { "\emph{" swap$ * "}" * }
docs/paper/aaai2026.bst:188:    { "\emph{" swap$ * "}" * }
docs/paper/introduction.tex:4:[Omitted long matching line]
docs/paper/introduction.tex:6:[Omitted long matching line]
docs/paper/introduction.tex:20:Counterintuitively, applying corrections without topology awareness can \emph{worsen} estimates: PPI++ harms M-bias by 88\% and topology-agnostic IV correction amplifies bias by 139\%.
docs/paper/method.tex:7:[Omitted long matching line]
docs/paper/method.tex:21:[Omitted long matching line]
docs/paper/method.tex:42:[Omitted long matching line]
docs/paper/method.tex:64:[Omitted long matching line]
docs/paper/method.tex:73:\emph{(a)}~Confounding preserves sign when $\operatorname{sign}(\tau) = \operatorname{sign}(\tau {+} B_{\mathrm{OV}})$, where $B_{\mathrm{OV}} {=} \operatorname{Cov}(g(A),f(A))/\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\ref{app:confounding}).
docs/paper/method.tex:74:\emph{(b)}~Collider preserves sign when $|\tau| > \sqrt{\operatorname{Var}(g)\operatorname{Var}(h)}/\mathbb{E}[\operatorname{Var}(T{\mid}A)]$ (Berkson attenuation; Appendix~\ref{app:collider}); empirically verified across 100{,}000 matrices with zero violations.
docs/paper/method.tex:75:\emph{(c)}~Exposure can produce sign reversal for $K {\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\ref{app:exposure}).
docs/paper/k3_symmetric_proof.tex:32:\emph{Verification.}
docs/paper/k3_symmetric_proof.tex:44:\emph{Derivation.}
docs/paper/k3_symmetric_proof.tex:62:\emph{Sign analysis.}
docs/paper/k3_symmetric_proof.tex:72:\emph{Strict inequality.}
docs/paper/k3_symmetric_proof.tex:116:The $K{=}3$ symmetric proof is \emph{stronger}:
docs/paper/e2e_real_cm_table.tex:22:\textit{Median improvement} & & \multicolumn{2}{c}{+93.6\%} & & \multicolumn{2}{c}{-0.0\%} \\
docs/paper/appendix_proofs.tex:183:If $|\tau| > \bar{B}$, then $\operatorname{sign}(\operatorname{plim}\hat\tau(C))=\operatorname{sign}(\tau)$ for \emph{all} column-stochastic $C$.
docs/paper/appendix_proofs.tex:190:\emph{Step 1: Bound $|R(C)|$.}
docs/paper/appendix_proofs.tex:206:\emph{Step 2: Conclude.}
docs/paper/appendix_proofs.tex:226:Since $|\tau|{=}2.0 > \bar{B}{=}0.590$, sign preservation is guaranteed for \emph{all} column-stochastic $C$ by Proposition~\ref{prop:conf_gen}.
docs/paper/appendix_proofs.tex:241:\emph{Step 1: Convexity of $V_B(\delta)$.}
docs/paper/appendix_proofs.tex:248:\emph{Step 2: Derivative formula.}
docs/paper/appendix_proofs.tex:256:\emph{Derivation.}
docs/paper/appendix_proofs.tex:261:\emph{Step 3: $V_B'(0)\leq 0$ (universal, no conditions on $C_0$).}
docs/paper/appendix_proofs.tex:270:\emph{Step 4: $V_B'(1)\leq 0$ for $K{=}2$.}
docs/paper/appendix_proofs.tex:286:\emph{Step 5: Monotonicity from convexity.}
docs/paper/appendix_proofs.tex:290:\emph{Step 6: $|B(\delta)|$ is non-decreasing.}
docs/paper/appendix_proofs.tex:308:Exact monotonicity ($V_B'(\delta) \leq 0$ for all $\delta$) holds under the \emph{component-wise diagonal dominance} condition:
docs/paper/appendix_proofs.tex:336:The key structural difference from confounding: $T$ \emph{causes} $A$, so the residual covariance $\operatorname{Cov}(T,f(A)\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.
docs/paper/appendix_proofs.tex:361:\emph{Endpoints.}
docs/paper/appendix_proofs.tex:365:\emph{Within-group structure for binary $T$.}
docs/paper/appendix_proofs.tex:373:Define $\delta_j=\mathbb{E}[f(A)\mid T{=}1,A^*{=}j]-\mathbb{E}[f(A)\mid T{=}0,A^*{=}j]$ as the \emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.
docs/paper/appendix_proofs.tex:385:\emph{Sign preservation.}
docs/paper/appendix_proofs.tex:405:\emph{Step 1: Decompose $T$ via the mediator.}
docs/paper/appendix_proofs.tex:412:\emph{Step 2: Reduce the numerator.}
docs/paper/appendix_proofs.tex:418:\emph{Step 3: Constant additive term in denominator.}
docs/paper/appendix_proofs.tex:424:This is \emph{constant} (independent of $C$):
docs/paper/appendix_proofs.tex:430:\emph{Step 4: Closed form and monotonicity.}
docs/paper/appendix_proofs.tex:438:The mediation bias~\eqref{eq:mediation} writes the residual indirect effect as $(1-\lambda(C))\,\tau_{\mathrm{ind}}$, which (for $\tau_{\mathrm{ind}}\neq 0$) \emph{implicitly} defines
docs/paper/appendix_proofs.tex:457:Under \emph{proportional effects} ($f(A)=\lambda_0\,g(A)$ with $g(k)=\mathbb{E}[T\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\lambda(C)\in[0,1]$ unconditionally.
docs/paper/appendix_proofs.tex:458:For \emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[f\mid A^*])$ may differ in sign or magnitude from $\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.
docs/paper/appendix_proofs.tex:461:[Omitted long matching line]
docs/paper/appendix_proofs.tex:465:\emph{(a),(b).} With $\tau_{\mathrm{ind}}\neq 0$, $\lambda(C)\leq 1\iff B(C)/\tau_{\mathrm{ind}}\geq 0\iff \operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$. Given (a), $\lambda(C)\geq 0\iff B(C)/\tau_{\mathrm{ind}}\leq 1\iff|B(C)|\leq|\tau_{\mathrm{ind}}|$.
docs/paper/appendix_proofs.tex:467:\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\lambda_0\,V_W(C)/(V_W(C)+\sigma_\varepsilon^2)$; the rank-one limit $V_W{\to}V$ yields $\tau_{\mathrm{ind}}=\lambda_0\,V/(V+\sigma_\varepsilon^2)$. Both quantities carry $\operatorname{sign}(\lambda_0)$, establishing~(a). The ratio
docs/paper/appendix_proofs.tex:473:\emph{General case.} Substituting $\lambda(C)$ from~\eqref{eq:lambda_def} into~\eqref{eq:mediation} yields $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)=\lambda(C)\,\tau_{\mathrm{dir}}+(1{-}\lambda(C))\,\tau_{\mathrm{total}}$, so $\lambda(C)\in[0,1]$ iff $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{total}}$.
docs/paper/appendix_proofs.tex:475:\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\mathbb{E}[T\mid A^*]=g(A)$, and FWL gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\tau_{\mathrm{dir}}$, hence $B(I)=0$ and $\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\perp A$ so $\mathbb{E}[T\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\operatorname{Cov}(Y,T)/\operatorname{Var}(T)=\tau_{\mathrm{total}}$, giving $B=\tau_{\mathrm{ind}}$ and $\lambda=0$.
docs/paper/appendix_proofs.tex:479:A natural \emph{diagnostic} closely related to $\lambda(C)$ is the between-variance ratio
docs/paper/appendix_proofs.tex:484:which satisfies $\lambda_V(C)\in[0,1]$ \emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\lambda$ and $\lambda_V$ agree at the endpoints and are related by
docs/paper/appendix_proofs.tex:493:\item \textbf{Proportional} ($f=\lambda_0\,g$, $\lambda_0\sim\mathcal{N}(0,1)\!\setminus\!\{0\}$): $\lambda(C)\in[0,1]$ in \emph{all} $30{,}000$ trials (pooled observed range $[1.2{\times}10^{-5},\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\hat\tau_{\mathrm{dir}}$ therefore reduces to $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
docs/paper/appendix_proofs.tex:519:The collider $A$ is a common \emph{effect} of $T$ and $Y$.
docs/paper/appendix_proofs.tex:579:\emph{Step~1: Bound the numerator.}
docs/paper/appendix_proofs.tex:584:\emph{Step~2: Bound the denominator.}
docs/paper/appendix_proofs.tex:587:\emph{Step~3: Conclude.}
docs/paper/appendix_proofs.tex:647:This decomposition reveals that \emph{misclassification does not affect the confounding component}.
docs/paper/appendix_proofs.tex:704:\emph{Marginal distribution of $A^*$:}
docs/paper/appendix_proofs.tex:711:\emph{Conditional means:}
docs/paper/appendix_proofs.tex:724:\emph{Estimated coefficient:}
docs/paper/appendix_proofs.tex:731:\emph{Mechanism.}
docs/paper/appendix_proofs.tex:767:\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.
docs/paper/appendix_proofs.tex:776:Once the condition is satisfied, sign preservation holds for \emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.
docs/paper/appendix_proofs.tex:885:(1)~\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;
docs/paper/appendix_proofs.tex:886:(2)~\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;
docs/paper/appendix_proofs.tex:887:(3)~\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;
docs/paper/appendix_proofs.tex:888:(4)~\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);
docs/paper/appendix_proofs.tex:889:(5)~\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;
docs/paper/appendix_proofs.tex:890:(6)~\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.
docs/paper/appendix_proofs.tex:978:Our taxonomy identifies this as a \emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.
docs/paper/appendix_proofs.tex:1018:The non-differential assumption $P(A^*{=}j \mid A{=}k, Y, \mathbf{Z}) = P(A^*{=}j \mid A{=}k)$ holds \emph{by design} in standard LLM annotation pipelines: the model receives only source text as input and classifies without observing the outcome $Y$ or covariates $\mathbf{Z}$. The annotation API call is structurally independent of downstream variables, satisfying the conditional independence requirement.
docs/paper/appendix_proofs.tex:1059:[Omitted long matching line]
docs/paper/appendix_proofs.tex:1163:[Omitted long matching line]
docs/paper/appendix_proofs.tex:1429:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9adbfcb4-f34c-46ac-9d0b-264e9bf8bcd5",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "a70f1ad8-ecc5-4c10-bc78-0d773c598fc9",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/related_work.tex:5:[Omitted long matching line]\ndocs/paper/main.bbl:7:\\newblock In \\emph{Proceedings of the International AAAI Conference on Web and\ndocs/paper/main.bbl:16:\\newblock \\emph{Science}, 382(6671):669--674.\ndocs/paper/main.bbl:23:\\newblock \\emph{Journal of the American Statistical Association},\ndocs/paper/main.bbl:31:\\newblock In \\emph{Proceedings of the 2025 Conference on Empirical Methods in\ndocs/paper/main.bbl:40:\\newblock \\emph{arXiv preprint arXiv:2509.08825}.\ndocs/paper/main.bbl:48:\\newblock \\emph{Oxford Bulletin of Economics and Statistics}, 86(4):951--993.\ndocs/paper/main.bbl:55:\\newblock \\emph{Sociological Methods \\& Research}, 46(3):303--341.\ndocs/paper/main.bbl:61:\\newblock In James~J. Heckman and Edward~E. Leamer, editors, \\emph{Handbook of\ndocs/paper/main.bbl:68:\\newblock \\emph{Journal of Clinical Epidemiology}, 46(1):57--63.\ndocs/paper/main.bbl:74:\\newblock \\emph{Biometrics}, 10(4):478--486.\ndocs/paper/main.bbl:78:\\newblock \\emph{Measurement Error: Models, Methods, and Applications}.\ndocs/paper/main.bbl:86:\\newblock \\emph{arXiv preprint arXiv:2502.06343}.\ndocs/paper/main.bbl:95:\\newblock \\emph{arXiv preprint arXiv:2601.02370}.\ndocs/paper/main.bbl:101:\\newblock \\emph{Measurement Error in Nonlinear Models: A Modern Perspective},\ndocs/paper/main.bbl:109:\\newblock \\emph{arXiv preprint arXiv:2412.14461}.\ndocs/paper/main.bbl:115:\\newblock \\emph{Journal of the Royal Statistical Society: Series B (Statistical\ndocs/paper/main.bbl:122:\\newblock In \\emph{Proceedings of the 41st International Conference on Machine\ndocs/paper/main.bbl:123:  Learning}, volume 235 of \\emph{Proceedings of Machine Learning Research},\ndocs/paper/main.bbl:130:\\newblock \\emph{Epidemiology}, 27(3):368--377.\ndocs/paper/main.bbl:137:\\newblock \\emph{American Journal of Epidemiology}, 132(4):746--748.\ndocs/paper/main.bbl:145:\\newblock \\emph{Annals of Epidemiology}, 58:104--123.\ndocs/paper/main.bbl:152:\\newblock In \\emph{Advances in Neural Information Processing Systems 36}.\ndocs/paper/main.bbl:163:\\newblock \\emph{Transactions of the Association for Computational Linguistics},\ndocs/paper/main.bbl:169:\\newblock \\emph{Econometrica}, 1(4):387--401.\ndocs/paper/main.bbl:176:\\newblock \\emph{Proceedings of the National Academy of Sciences},\ndocs/paper/main.bbl:184:\\newblock In \\emph{Proceedings of the 2025 Conference of the North American\ndocs/paper/main.bbl:192:\\newblock \\emph{Epidemiology}, 14:300--306.\ndocs/paper/main.bbl:196:\\newblock \\emph{Text as Data: A New Framework for Machine Learning and the\ndocs/paper/main.bbl:202:\\newblock \\emph{Measurement Error and Misclassification in Statistics and\ndocs/paper/main.bbl:210:\\newblock \\emph{American Journal of Epidemiology}, 170(8):959--962.\ndocs/paper/main.bbl:214:\\newblock \\emph{Causal Inference: What If}.\ndocs/paper/main.bbl:222:\\newblock \\emph{Journal of Econometrics}, 144(1):27--61.\ndocs/paper/main.bbl:228:\\newblock \\emph{Statistical Science}, 25(1):51--71.\ndocs/paper/main.bbl:234:\\newblock \\emph{American Journal of Political Science}, 54(2):543--560.\ndocs/paper/main.bbl:241:\\newblock \\emph{International Journal of Epidemiology}, 34(3):680--687.\ndocs/paper/main.bbl:249:\\newblock In \\emph{Proceedings of the 58th Annual Meeting of the Association\ndocs/paper/main.bbl:255:\\newblock In \\emph{Proceedings of the 42nd International Conference on Machine\ndocs/paper/main.bbl:263:\\newblock \\emph{Biometrics}, 62(1):85--96.\ndocs/paper/main.bbl:269:\\newblock \\emph{Biometrika}, 101(2):423--437.\ndocs/paper/main.bbl:273:\\newblock \\href {https://doi.org/10.1007/978-0-387-87959-8} {\\emph{Applying\ndocs/paper/main.bbl:281:\\newblock In \\emph{AIM-FM Workshop, NeurIPS 2024}.\ndocs/paper/main.bbl:288:\\newblock \\emph{Journal of the American Statistical Association},\ndocs/paper/main.bbl:295:\\newblock \\emph{Econometrica}, 74(3):631--665.\ndocs/paper/main.bbl:302:\\newblock \\emph{Epidemiology}, 29(5):e45--e47.\ndocs/paper/main.bbl:308:\\newblock \\emph{arXiv preprint arXiv:2604.11581}.\ndocs/paper/main.bbl:314:\\newblock \\emph{Journal of Econometrics}, 208(2):487--506.\ndocs/paper/main.bbl:320:\\newblock \\emph{Epidemiology}, 23(3):433--439.\ndocs/paper/main.bbl:326:\\newblock \\emph{Journal of Business \\& Economic Statistics}, 37(2):187--204.\ndocs/paper/main.bbl:332:\\newblock \\emph{arXiv preprint arXiv:2306.00176}.\ndocs/paper/main.bbl:336:\\newblock \\emph{Causality: Models, Reasoning and Inference}, 2nd edition.\ndocs/paper/main.bbl:345:\\newblock In \\emph{Proceedings of the 2021 Conference of the North American\ndocs/paper/main.bbl:353:  Rosa~L. Matzkin, editors, \\emph{Handbook of Econometrics}, volume~7A, pages\ndocs/paper/main.bbl:360:\\newblock \\emph{Statistical Methods in Medical Research}, 28(7):2049--2068.\ndocs/paper/main.bbl:366:\\newblock \\emph{Statistics in Medicine}, 38(10):1835--1854.\ndocs/paper/main.bbl:372:\\newblock \\emph{The Annals of Statistics}, 13(4):1335--1351.\ndocs/paper/main.bbl:379:\\newblock In \\emph{Proceedings of the 2024 Conference on Empirical Methods in\ndocs/paper/main.bbl:388:\\newblock \\emph{Communication Methods and Measures}, 18(3):278--299.\ndocs/paper/main.bbl:395:\\newblock \\emph{Psychological Methods}, 18(2):137--150.\ndocs/paper/main.bbl:399:\\newblock \\emph{Explanation in Causal Inference: Methods for Mediation and\ndocs/paper/main.bbl:407:\\newblock \\emph{Annals of Internal Medicine}, 167:268--274.\ndocs/paper/main.bbl:413:\\newblock \\emph{Statistics in Medicine}, 20(5):771--784.\ndocs/paper/main.bbl:419:\\newblock \\emph{Statistical Methods in Medical Research}.\ndocs/paper/main.bbl:426:\\newblock In \\emph{Proceedings of the 2018 Conference on Empirical Methods in\ndocs/paper/main.bbl:435:\\newblock \\emph{Computational Linguistics}, 50(1):237--291.\ndocs/paper/main.bbl:441:\\newblock \\emph{Proceedings of the National Academy of Sciences}.\ndocs/paper/acl_natbib.bst:378:    { \"\\emph{\" swap$ * \"}\" * }\ndocs/paper/aaai2026.bst:188:    { \"\\emph{\" swap$ * \"}\" * }\ndocs/paper/introduction.tex:4:[Omitted long matching line]\ndocs/paper/introduction.tex:6:[Omitted long matching line]\ndocs/paper/introduction.tex:20:Counterintuitively, applying corrections without topology awareness can \\emph{worsen} estimates: PPI++ harms M-bias by 88\\% and topology-agnostic IV correction amplifies bias by 139\\%.\ndocs/paper/method.tex:7:[Omitted long matching line]\ndocs/paper/method.tex:21:[Omitted long matching line]\ndocs/paper/method.tex:42:[Omitted long matching line]\ndocs/paper/method.tex:64:[Omitted long matching line]\ndocs/paper/method.tex:73:\\emph{(a)}~Confounding preserves sign when $\\operatorname{sign}(\\tau) = \\operatorname{sign}(\\tau {+} B_{\\mathrm{OV}})$, where $B_{\\mathrm{OV}} {=} \\operatorname{Cov}(g(A),f(A))/\\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\\ref{app:confounding}).\ndocs/paper/method.tex:74:\\emph{(b)}~Collider preserves sign when $|\\tau| > \\sqrt{\\operatorname{Var}(g)\\operatorname{Var}(h)}/\\mathbb{E}[\\operatorname{Var}(T{\\mid}A)]$ (Berkson attenuation; Appendix~\\ref{app:collider}); empirically verified across 100{,}000 matrices with zero violations.\ndocs/paper/method.tex:75:\\emph{(c)}~Exposure can produce sign reversal for $K {\\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\\ref{app:exposure}).\ndocs/paper/k3_symmetric_proof.tex:32:\\emph{Verification.}\ndocs/paper/k3_symmetric_proof.tex:44:\\emph{Derivation.}\ndocs/paper/k3_symmetric_proof.tex:62:\\emph{Sign analysis.}\ndocs/paper/k3_symmetric_proof.tex:72:\\emph{Strict inequality.}\ndocs/paper/k3_symmetric_proof.tex:116:The $K{=}3$ symmetric proof is \\emph{stronger}:\ndocs/paper/e2e_real_cm_table.tex:22:\\textit{Median improvement} & & \\multicolumn{2}{c}{+93.6\\%} & & \\multicolumn{2}{c}{-0.0\\%} \\\\\ndocs/paper/appendix_proofs.tex:183:If $|\\tau| > \\bar{B}$, then $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau(C))=\\operatorname{sign}(\\tau)$ for \\emph{all} column-stochastic $C$.\ndocs/paper/appendix_proofs.tex:190:\\emph{Step 1: Bound $|R(C)|$.}\ndocs/paper/appendix_proofs.tex:206:\\emph{Step 2: Conclude.}\ndocs/paper/appendix_proofs.tex:226:Since $|\\tau|{=}2.0 > \\bar{B}{=}0.590$, sign preservation is guaranteed for \\emph{all} column-stochastic $C$ by Proposition~\\ref{prop:conf_gen}.\ndocs/paper/appendix_proofs.tex:241:\\emph{Step 1: Convexity of $V_B(\\delta)$.}\ndocs/paper/appendix_proofs.tex:248:\\emph{Step 2: Derivative formula.}\ndocs/paper/appendix_proofs.tex:256:\\emph{Derivation.}\ndocs/paper/appendix_proofs.tex:261:\\emph{Step 3: $V_B'(0)\\leq 0$ (universal, no conditions on $C_0$).}\ndocs/paper/appendix_proofs.tex:270:\\emph{Step 4: $V_B'(1)\\leq 0$ for $K{=}2$.}\ndocs/paper/appendix_proofs.tex:286:\\emph{Step 5: Monotonicity from convexity.}\ndocs/paper/appendix_proofs.tex:290:\\emph{Step 6: $|B(\\delta)|$ is non-decreasing.}\ndocs/paper/appendix_proofs.tex:308:Exact monotonicity ($V_B'(\\delta) \\leq 0$ for all $\\delta$) holds under the \\emph{component-wise diagonal dominance} condition:\ndocs/paper/appendix_proofs.tex:336:The key structural difference from confounding: $T$ \\emph{causes} $A$, so the residual covariance $\\operatorname{Cov}(T,f(A)\\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.\ndocs/paper/appendix_proofs.tex:361:\\emph{Endpoints.}\ndocs/paper/appendix_proofs.tex:365:\\emph{Within-group structure for binary $T$.}\ndocs/paper/appendix_proofs.tex:373:Define $\\delta_j=\\mathbb{E}[f(A)\\mid T{=}1,A^*{=}j]-\\mathbb{E}[f(A)\\mid T{=}0,A^*{=}j]$ as the \\emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.\ndocs/paper/appendix_proofs.tex:385:\\emph{Sign preservation.}\ndocs/paper/appendix_proofs.tex:405:\\emph{Step 1: Decompose $T$ via the mediator.}\ndocs/paper/appendix_proofs.tex:412:\\emph{Step 2: Reduce the numerator.}\ndocs/paper/appendix_proofs.tex:418:\\emph{Step 3: Constant additive term in denominator.}\ndocs/paper/appendix_proofs.tex:424:This is \\emph{constant} (independent of $C$):\ndocs/paper/appendix_proofs.tex:430:\\emph{Step 4: Closed form and monotonicity.}\ndocs/paper/appendix_proofs.tex:438:The mediation bias~\\eqref{eq:mediation} writes the residual indirect effect as $(1-\\lambda(C))\\,\\tau_{\\mathrm{ind}}$, which (for $\\tau_{\\mathrm{ind}}\\neq 0$) \\emph{implicitly} defines\ndocs/paper/appendix_proofs.tex:457:Under \\emph{proportional effects} ($f(A)=\\lambda_0\\,g(A)$ with $g(k)=\\mathbb{E}[T\\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\\lambda(C)\\in[0,1]$ unconditionally.\ndocs/paper/appendix_proofs.tex:458:For \\emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[f\\mid A^*])$ may differ in sign or magnitude from $\\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.\ndocs/paper/appendix_proofs.tex:461:[Omitted long matching line]\ndocs/paper/appendix_proofs.tex:465:\\emph{(a),(b).} With $\\tau_{\\mathrm{ind}}\\neq 0$, $\\lambda(C)\\leq 1\\iff B(C)/\\tau_{\\mathrm{ind}}\\geq 0\\iff \\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$. Given (a), $\\lambda(C)\\geq 0\\iff B(C)/\\tau_{\\mathrm{ind}}\\leq 1\\iff|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$.\ndocs/paper/appendix_proofs.tex:467:\\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\\lambda_0\\,V_W(C)/(V_W(C)+\\sigma_\\varepsilon^2)$; the rank-one limit $V_W{\\to}V$ yields $\\tau_{\\mathrm{ind}}=\\lambda_0\\,V/(V+\\sigma_\\varepsilon^2)$. Both quantities carry $\\operatorname{sign}(\\lambda_0)$, establishing~(a). The ratio\ndocs/paper/appendix_proofs.tex:473:\\emph{General case.} Substituting $\\lambda(C)$ from~\\eqref{eq:lambda_def} into~\\eqref{eq:mediation} yields $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)=\\lambda(C)\\,\\tau_{\\mathrm{dir}}+(1{-}\\lambda(C))\\,\\tau_{\\mathrm{total}}$, so $\\lambda(C)\\in[0,1]$ iff $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{total}}$.\ndocs/paper/appendix_proofs.tex:475:\\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\\mathbb{E}[T\\mid A^*]=g(A)$, and FWL gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\tau_{\\mathrm{dir}}$, hence $B(I)=0$ and $\\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\\perp A$ so $\\mathbb{E}[T\\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\operatorname{Cov}(Y,T)/\\operatorname{Var}(T)=\\tau_{\\mathrm{total}}$, giving $B=\\tau_{\\mathrm{ind}}$ and $\\lambda=0$.\ndocs/paper/appendix_proofs.tex:479:A natural \\emph{diagnostic} closely related to $\\lambda(C)$ is the between-variance ratio\ndocs/paper/appendix_proofs.tex:484:which satisfies $\\lambda_V(C)\\in[0,1]$ \\emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\\lambda$ and $\\lambda_V$ agree at the endpoints and are related by\ndocs/paper/appendix_proofs.tex:493:\\item \\textbf{Proportional} ($f=\\lambda_0\\,g$, $\\lambda_0\\sim\\mathcal{N}(0,1)\\!\\setminus\\!\\{0\\}$): $\\lambda(C)\\in[0,1]$ in \\emph{all} $30{,}000$ trials (pooled observed range $[1.2{\\times}10^{-5},\\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ therefore reduces to $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\ndocs/paper/appendix_proofs.tex:519:The collider $A$ is a common \\emph{effect} of $T$ and $Y$.\ndocs/paper/appendix_proofs.tex:579:\\emph{Step~1: Bound the numerator.}\ndocs/paper/appendix_proofs.tex:584:\\emph{Step~2: Bound the denominator.}\ndocs/paper/appendix_proofs.tex:587:\\emph{Step~3: Conclude.}\ndocs/paper/appendix_proofs.tex:647:This decomposition reveals that \\emph{misclassification does not affect the confounding component}.\ndocs/paper/appendix_proofs.tex:704:\\emph{Marginal distribution of $A^*$:}\ndocs/paper/appendix_proofs.tex:711:\\emph{Conditional means:}\ndocs/paper/appendix_proofs.tex:724:\\emph{Estimated coefficient:}\ndocs/paper/appendix_proofs.tex:731:\\emph{Mechanism.}\ndocs/paper/appendix_proofs.tex:767:\\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.\ndocs/paper/appendix_proofs.tex:776:Once the condition is satisfied, sign preservation holds for \\emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.\ndocs/paper/appendix_proofs.tex:885:(1)~\\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;\ndocs/paper/appendix_proofs.tex:886:(2)~\\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;\ndocs/paper/appendix_proofs.tex:887:(3)~\\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;\ndocs/paper/appendix_proofs.tex:888:(4)~\\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);\ndocs/paper/appendix_proofs.tex:889:(5)~\\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;\ndocs/paper/appendix_proofs.tex:890:(6)~\\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.\ndocs/paper/appendix_proofs.tex:978:Our taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.\ndocs/paper/appendix_proofs.tex:1018:The non-differential assumption $P(A^*{=}j \\mid A{=}k, Y, \\mathbf{Z}) = P(A^*{=}j \\mid A{=}k)$ holds \\emph{by design} in standard LLM annotation pipelines: the model receives only source text as input and classifies without observing the outcome $Y$ or covariates $\\mathbf{Z}$. The annotation API call is structurally independent of downstream variables, satisfying the conditional independence requirement.\ndocs/paper/appendix_proofs.tex:1059:[Omitted long matching line]\ndocs/paper/appendix_proofs.tex:1163:[Omitted long matching line]\ndocs/paper/appendix_proofs.tex:1429:[Omitted long matching line]",
    "numLines": 139
  },
  "sourceToolAssistantUUID": "9adbfcb4-f34c-46ac-9d0b-264e9bf8bcd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-24T06:35:40.906Z_

<details open><summary>🔧 Tool call — Read · `toolu_01QWVpx7qean4mgznWjeoDo8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a70f1ad8-ecc5-4c10-bc78-0d773c598fc9",
  "isSidechain": false,
  "requestId": "req_011CbLvtc9kokrDmBWTTQS3L",
  "type": "assistant",
  "uuid": "59111cf5-62e0-47a3-bd35-1565c654d3c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FVnv1xHA7QfFELUxtWKMx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17018,
      "cache_read_input_tokens": 25849,
      "output_tokens": 322,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17018,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 322,
          "cache_read_input_tokens": 25849,
          "cache_creation_input_tokens": 17018,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17018
          },
          "type": "message"
        }
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

_source line 39_

```json
{
  "type": "last-prompt",
  "leafUuid": "ca235f53-8a6b-42d8-99d6-68e01cfb7585",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 40_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 41 · 2026-05-24T06:36:06.883Z_

<details><summary>Logged reasoning block</summary>

```text
Let me analyze the italic usage I found. Let me categorize each instance:

**introduction.tex:**
1. Line 4: `\emph{structure}` — emphasizing a key concept contrast ("structure vs magnitude"). This is a genuine emphasis on the first mention of the key insight. Legitimate.
2. Line 6: `\emph{vanishes}` — emphasizing a key result (the guarantee vanishes). Legitimate emphasis.
3. Line 20: `\emph{worsen}` — emphasizing counterintuitive result. Legitimate emphasis.

**method.tex:**
4. Line 7: `\emph{starred-node}` — first definition of a technical term. Legitimate.


5. Line 21: `\emph{linear}` — emphasizing scope. Legitimate emphasis.
6. Line 42: `\emph{sign reversal}` — this appears in the exposure paragraph, but I need to verify if it's truly a first definitional use since "sign reversal" already appears unemphasized in the introduction.
7. Line 64: `\emph{protective}` or `\emph{immune}` — these are first definitions in the taxonomy section, so the emphasis is justified.

8. Lines 73-75: `\emph{(a)}`, `\emph{(b)}`, `\emph{(c)}` — standard proposition label formatting, legitimate use.

Moving through the proof files now. In k3_symmetric_proof.tex, I'm seeing `\emph{}` used consistently for proof section headings like "Verification," "Derivation," "Sign analysis," and "Strict inequality" — all legitimate structural markers. There's also `\emph{stronger}` for emphasis in a comparison, which works. The appendix_proofs.tex file has multiple instances of `\emph{}` throughout the proof steps.

Looking at the full context of these uses, they cluster into a few clear patterns: proof step headers, first mentions of key terms like "starred-node" and "protective," and emphasis on critical logical words within propositions. The bibliography entries are separate. Most of these are standard mathematical writing conventions.

Now I'm checking for actual problems—like `\textit{Median improvement}` in the table file, which seems like an odd choice for italics, and whether any terms are getting italicized repeatedly without good reason. Let me dig into the appendix more systematically to spot what's actually problematic.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ca235f53-8a6b-42d8-99d6-68e01cfb7585",
  "isSidechain": false,
  "requestId": "req_011CbLvu9xSVNWZtvN6wcVVm",
  "type": "assistant",
  "uuid": "dffee518-00a9-4ff6-834b-9b03561e929f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRZzeEZuEnpE7J5osqnybi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11815,
      "cache_read_input_tokens": 42867,
      "output_tokens": 1374,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11815,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1374,
          "cache_read_input_tokens": 42867,
          "cache_creation_input_tokens": 11815,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11815
          },
          "type": "message"
        }
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

_source line 42 · 2026-05-24T06:36:06.885Z_

Let me search for specific italic patterns and read the remaining appendix sections.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dffee518-00a9-4ff6-834b-9b03561e929f",
  "isSidechain": false,
  "requestId": "req_011CbLvu9xSVNWZtvN6wcVVm",
  "type": "assistant",
  "uuid": "08760cad-8909-490f-a9f2-edd1b638d17e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRZzeEZuEnpE7J5osqnybi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11815,
      "cache_read_input_tokens": 42867,
      "output_tokens": 1374,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11815,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1374,
          "cache_read_input_tokens": 42867,
          "cache_creation_input_tokens": 11815,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11815
          },
          "type": "message"
        }
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

_source line 43 · 2026-05-24T06:36:09.117Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01FXZ61p52E6JPgE91ZagcNe`</summary>

```json
{
  "pattern": "\\\\textit\\{",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "output_mode": "content",
  "-n": true,
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "08760cad-8909-490f-a9f2-edd1b638d17e",
  "isSidechain": false,
  "requestId": "req_011CbLvu9xSVNWZtvN6wcVVm",
  "type": "assistant",
  "uuid": "c34db5e8-52ec-4909-b7c0-f1c456ba5f89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRZzeEZuEnpE7J5osqnybi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11815,
      "cache_read_input_tokens": 42867,
      "output_tokens": 1374,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11815,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1374,
          "cache_read_input_tokens": 42867,
          "cache_creation_input_tokens": 11815,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11815
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-24T06:36:10.059Z_

<details><summary>↩ Tool result · `toolu_01RQcMYYGYNMQJ6KxHJ3GPZa`</summary>

```text
docs/paper/related_work.tex:5:[Omitted long matching line]
docs/paper/method.tex:7:[Omitted long matching line]
docs/paper/method.tex:21:[Omitted long matching line]
docs/paper/method.tex:42:[Omitted long matching line]
docs/paper/method.tex:64:[Omitted long matching line]
docs/paper/method.tex:73:\emph{(a)}~Confounding preserves sign when $\operatorname{sign}(\tau) = \operatorname{sign}(\tau {+} B_{\mathrm{OV}})$, where $B_{\mathrm{OV}} {=} \operatorname{Cov}(g(A),f(A))/\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\ref{app:confounding}).
docs/paper/method.tex:74:\emph{(b)}~Collider preserves sign when $|\tau| > \sqrt{\operatorname{Var}(g)\operatorname{Var}(h)}/\mathbb{E}[\operatorname{Var}(T{\mid}A)]$ (Berkson attenuation; Appendix~\ref{app:collider}); empirically verified across 100{,}000 matrices with zero violations.
docs/paper/method.tex:75:\emph{(c)}~Exposure can produce sign reversal for $K {\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\ref{app:exposure}).
docs/paper/k3_symmetric_proof.tex:32:\emph{Verification.}
docs/paper/k3_symmetric_proof.tex:44:\emph{Derivation.}
docs/paper/k3_symmetric_proof.tex:62:\emph{Sign analysis.}
docs/paper/k3_symmetric_proof.tex:72:\emph{Strict inequality.}
docs/paper/k3_symmetric_proof.tex:116:The $K{=}3$ symmetric proof is \emph{stronger}:
docs/paper/appendix_proofs.tex:183:If $|\tau| > \bar{B}$, then $\operatorname{sign}(\operatorname{plim}\hat\tau(C))=\operatorname{sign}(\tau)$ for \emph{all} column-stochastic $C$.
docs/paper/appendix_proofs.tex:190:\emph{Step 1: Bound $|R(C)|$.}
docs/paper/appendix_proofs.tex:206:\emph{Step 2: Conclude.}
docs/paper/appendix_proofs.tex:226:Since $|\tau|{=}2.0 > \bar{B}{=}0.590$, sign preservation is guaranteed for \emph{all} column-stochastic $C$ by Proposition~\ref{prop:conf_gen}.
docs/paper/appendix_proofs.tex:241:\emph{Step 1: Convexity of $V_B(\delta)$.}
docs/paper/appendix_proofs.tex:248:\emph{Step 2: Derivative formula.}
docs/paper/appendix_proofs.tex:256:\emph{Derivation.}
docs/paper/appendix_proofs.tex:261:\emph{Step 3: $V_B'(0)\leq 0$ (universal, no conditions on $C_0$).}
docs/paper/appendix_proofs.tex:270:\emph{Step 4: $V_B'(1)\leq 0$ for $K{=}2$.}
docs/paper/appendix_proofs.tex:286:\emph{Step 5: Monotonicity from convexity.}
docs/paper/appendix_proofs.tex:290:\emph{Step 6: $|B(\delta)|$ is non-decreasing.}
docs/paper/appendix_proofs.tex:308:Exact monotonicity ($V_B'(\delta) \leq 0$ for all $\delta$) holds under the \emph{component-wise diagonal dominance} condition:
docs/paper/appendix_proofs.tex:336:The key structural difference from confounding: $T$ \emph{causes} $A$, so the residual covariance $\operatorname{Cov}(T,f(A)\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.
docs/paper/appendix_proofs.tex:361:\emph{Endpoints.}
docs/paper/appendix_proofs.tex:365:\emph{Within-group structure for binary $T$.}
docs/paper/appendix_proofs.tex:373:Define $\delta_j=\mathbb{E}[f(A)\mid T{=}1,A^*{=}j]-\mathbb{E}[f(A)\mid T{=}0,A^*{=}j]$ as the \emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.
docs/paper/appendix_proofs.tex:385:\emph{Sign preservation.}
docs/paper/appendix_proofs.tex:405:\emph{Step 1: Decompose $T$ via the mediator.}
docs/paper/appendix_proofs.tex:412:\emph{Step 2: Reduce the numerator.}
docs/paper/appendix_proofs.tex:418:\emph{Step 3: Constant additive term in denominator.}
docs/paper/appendix_proofs.tex:424:This is \emph{constant} (independent of $C$):
docs/paper/appendix_proofs.tex:430:\emph{Step 4: Closed form and monotonicity.}
docs/paper/appendix_proofs.tex:438:The mediation bias~\eqref{eq:mediation} writes the residual indirect effect as $(1-\lambda(C))\,\tau_{\mathrm{ind}}$, which (for $\tau_{\mathrm{ind}}\neq 0$) \emph{implicitly} defines
docs/paper/appendix_proofs.tex:457:Under \emph{proportional effects} ($f(A)=\lambda_0\,g(A)$ with $g(k)=\mathbb{E}[T\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\lambda(C)\in[0,1]$ unconditionally.
docs/paper/appendix_proofs.tex:458:For \emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[f\mid A^*])$ may differ in sign or magnitude from $\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.
docs/paper/appendix_proofs.tex:461:[Omitted long matching line]
docs/paper/appendix_proofs.tex:465:\emph{(a),(b).} With $\tau_{\mathrm{ind}}\neq 0$, $\lambda(C)\leq 1\iff B(C)/\tau_{\mathrm{ind}}\geq 0\iff \operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$. Given (a), $\lambda(C)\geq 0\iff B(C)/\tau_{\mathrm{ind}}\leq 1\iff|B(C)|\leq|\tau_{\mathrm{ind}}|$.
docs/paper/appendix_proofs.tex:467:\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\lambda_0\,V_W(C)/(V_W(C)+\sigma_\varepsilon^2)$; the rank-one limit $V_W{\to}V$ yields $\tau_{\mathrm{ind}}=\lambda_0\,V/(V+\sigma_\varepsilon^2)$. Both quantities carry $\operatorname{sign}(\lambda_0)$, establishing~(a). The ratio
docs/paper/appendix_proofs.tex:473:\emph{General case.} Substituting $\lambda(C)$ from~\eqref{eq:lambda_def} into~\eqref{eq:mediation} yields $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)=\lambda(C)\,\tau_{\mathrm{dir}}+(1{-}\lambda(C))\,\tau_{\mathrm{total}}$, so $\lambda(C)\in[0,1]$ iff $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{total}}$.
docs/paper/appendix_proofs.tex:475:\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\mathbb{E}[T\mid A^*]=g(A)$, and FWL gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\tau_{\mathrm{dir}}$, hence $B(I)=0$ and $\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\perp A$ so $\mathbb{E}[T\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\operatorname{Cov}(Y,T)/\operatorname{Var}(T)=\tau_{\mathrm{total}}$, giving $B=\tau_{\mathrm{ind}}$ and $\lambda=0$.
docs/paper/appendix_proofs.tex:479:A natural \emph{diagnostic} closely related to $\lambda(C)$ is the between-variance ratio
docs/paper/appendix_proofs.tex:484:which satisfies $\lambda_V(C)\in[0,1]$ \emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\lambda$ and $\lambda_V$ agree at the endpoints and are related by
docs/paper/appendix_proofs.tex:493:\item \textbf{Proportional} ($f=\lambda_0\,g$, $\lambda_0\sim\mathcal{N}(0,1)\!\setminus\!\{0\}$): $\lambda(C)\in[0,1]$ in \emph{all} $30{,}000$ trials (pooled observed range $[1.2{\times}10^{-5},\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\hat\tau_{\mathrm{dir}}$ therefore reduces to $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
docs/paper/appendix_proofs.tex:519:The collider $A$ is a common \emph{effect} of $T$ and $Y$.
docs/paper/appendix_proofs.tex:579:\emph{Step~1: Bound the numerator.}
docs/paper/appendix_proofs.tex:584:\emph{Step~2: Bound the denominator.}
docs/paper/appendix_proofs.tex:587:\emph{Step~3: Conclude.}
docs/paper/appendix_proofs.tex:647:This decomposition reveals that \emph{misclassification does not affect the confounding component}.
docs/paper/appendix_proofs.tex:704:\emph{Marginal distribution of $A^*$:}
docs/paper/appendix_proofs.tex:711:\emph{Conditional means:}
docs/paper/appendix_proofs.tex:724:\emph{Estimated coefficient:}
docs/paper/appendix_proofs.tex:731:\emph{Mechanism.}
docs/paper/appendix_proofs.tex:767:\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.
docs/paper/appendix_proofs.tex:776:Once the condition is satisfied, sign preservation holds for \emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.
docs/paper/appendix_proofs.tex:885:(1)~\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;
docs/paper/appendix_proofs.tex:886:(2)~\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;
docs/paper/appendix_proofs.tex:887:(3)~\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;
docs/paper/appendix_proofs.tex:888:(4)~\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);
docs/paper/appendix_proofs.tex:889:(5)~\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;
docs/paper/appendix_proofs.tex:890:(6)~\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.
docs/paper/appendix_proofs.tex:978:Our taxonomy identifies this as a \emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.
docs/paper/appendix_proofs.tex:1018:The non-differential assumption $P(A^*{=}j \mid A{=}k, Y, \mathbf{Z}) = P(A^*{=}j \mid A{=}k)$ holds \emph{by design} in standard LLM annotation pipelines: the model receives only source text as input and classifies without observing the outcome $Y$ or covariates $\mathbf{Z}$. The annotation API call is structurally independent of downstream variables, satisfying the conditional independence requirement.
docs/paper/appendix_proofs.tex:1059:[Omitted long matching line]
docs/paper/appendix_proofs.tex:1163:[Omitted long matching line]
docs/paper/appendix_proofs.tex:1429:[Omitted long matching line]
docs/paper/introduction.tex:4:[Omitted long matching line]
docs/paper/introduction.tex:6:[Omitted long matching line]
docs/paper/introduction.tex:20:Counterintuitively, applying corrections without topology awareness can \emph{worsen} estimates: PPI++ harms M-bias by 88\% and topology-agnostic IV correction amplifies bias by 139\%.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "94f44cd4-3312-455b-a2af-a67bb96bb6a8",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "1e801d34-6875-4c83-b6cf-b5689b65e166",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/related_work.tex:5:[Omitted long matching line]\ndocs/paper/method.tex:7:[Omitted long matching line]\ndocs/paper/method.tex:21:[Omitted long matching line]\ndocs/paper/method.tex:42:[Omitted long matching line]\ndocs/paper/method.tex:64:[Omitted long matching line]\ndocs/paper/method.tex:73:\\emph{(a)}~Confounding preserves sign when $\\operatorname{sign}(\\tau) = \\operatorname{sign}(\\tau {+} B_{\\mathrm{OV}})$, where $B_{\\mathrm{OV}} {=} \\operatorname{Cov}(g(A),f(A))/\\operatorname{Var}(T)$ is the omitted-variable bias (Cauchy--Schwarz; Appendix~\\ref{app:confounding}).\ndocs/paper/method.tex:74:\\emph{(b)}~Collider preserves sign when $|\\tau| > \\sqrt{\\operatorname{Var}(g)\\operatorname{Var}(h)}/\\mathbb{E}[\\operatorname{Var}(T{\\mid}A)]$ (Berkson attenuation; Appendix~\\ref{app:collider}); empirically verified across 100{,}000 matrices with zero violations.\ndocs/paper/method.tex:75:\\emph{(c)}~Exposure can produce sign reversal for $K {\\geq} 3$, even with $C_{kk} {>} 0.5$ (counterexample in Appendix~\\ref{app:exposure}).\ndocs/paper/k3_symmetric_proof.tex:32:\\emph{Verification.}\ndocs/paper/k3_symmetric_proof.tex:44:\\emph{Derivation.}\ndocs/paper/k3_symmetric_proof.tex:62:\\emph{Sign analysis.}\ndocs/paper/k3_symmetric_proof.tex:72:\\emph{Strict inequality.}\ndocs/paper/k3_symmetric_proof.tex:116:The $K{=}3$ symmetric proof is \\emph{stronger}:\ndocs/paper/appendix_proofs.tex:183:If $|\\tau| > \\bar{B}$, then $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau(C))=\\operatorname{sign}(\\tau)$ for \\emph{all} column-stochastic $C$.\ndocs/paper/appendix_proofs.tex:190:\\emph{Step 1: Bound $|R(C)|$.}\ndocs/paper/appendix_proofs.tex:206:\\emph{Step 2: Conclude.}\ndocs/paper/appendix_proofs.tex:226:Since $|\\tau|{=}2.0 > \\bar{B}{=}0.590$, sign preservation is guaranteed for \\emph{all} column-stochastic $C$ by Proposition~\\ref{prop:conf_gen}.\ndocs/paper/appendix_proofs.tex:241:\\emph{Step 1: Convexity of $V_B(\\delta)$.}\ndocs/paper/appendix_proofs.tex:248:\\emph{Step 2: Derivative formula.}\ndocs/paper/appendix_proofs.tex:256:\\emph{Derivation.}\ndocs/paper/appendix_proofs.tex:261:\\emph{Step 3: $V_B'(0)\\leq 0$ (universal, no conditions on $C_0$).}\ndocs/paper/appendix_proofs.tex:270:\\emph{Step 4: $V_B'(1)\\leq 0$ for $K{=}2$.}\ndocs/paper/appendix_proofs.tex:286:\\emph{Step 5: Monotonicity from convexity.}\ndocs/paper/appendix_proofs.tex:290:\\emph{Step 6: $|B(\\delta)|$ is non-decreasing.}\ndocs/paper/appendix_proofs.tex:308:Exact monotonicity ($V_B'(\\delta) \\leq 0$ for all $\\delta$) holds under the \\emph{component-wise diagonal dominance} condition:\ndocs/paper/appendix_proofs.tex:336:The key structural difference from confounding: $T$ \\emph{causes} $A$, so the residual covariance $\\operatorname{Cov}(T,f(A)\\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.\ndocs/paper/appendix_proofs.tex:361:\\emph{Endpoints.}\ndocs/paper/appendix_proofs.tex:365:\\emph{Within-group structure for binary $T$.}\ndocs/paper/appendix_proofs.tex:373:Define $\\delta_j=\\mathbb{E}[f(A)\\mid T{=}1,A^*{=}j]-\\mathbb{E}[f(A)\\mid T{=}0,A^*{=}j]$ as the \\emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.\ndocs/paper/appendix_proofs.tex:385:\\emph{Sign preservation.}\ndocs/paper/appendix_proofs.tex:405:\\emph{Step 1: Decompose $T$ via the mediator.}\ndocs/paper/appendix_proofs.tex:412:\\emph{Step 2: Reduce the numerator.}\ndocs/paper/appendix_proofs.tex:418:\\emph{Step 3: Constant additive term in denominator.}\ndocs/paper/appendix_proofs.tex:424:This is \\emph{constant} (independent of $C$):\ndocs/paper/appendix_proofs.tex:430:\\emph{Step 4: Closed form and monotonicity.}\ndocs/paper/appendix_proofs.tex:438:The mediation bias~\\eqref{eq:mediation} writes the residual indirect effect as $(1-\\lambda(C))\\,\\tau_{\\mathrm{ind}}$, which (for $\\tau_{\\mathrm{ind}}\\neq 0$) \\emph{implicitly} defines\ndocs/paper/appendix_proofs.tex:457:Under \\emph{proportional effects} ($f(A)=\\lambda_0\\,g(A)$ with $g(k)=\\mathbb{E}[T\\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\\lambda(C)\\in[0,1]$ unconditionally.\ndocs/paper/appendix_proofs.tex:458:For \\emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[f\\mid A^*])$ may differ in sign or magnitude from $\\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.\ndocs/paper/appendix_proofs.tex:461:[Omitted long matching line]\ndocs/paper/appendix_proofs.tex:465:\\emph{(a),(b).} With $\\tau_{\\mathrm{ind}}\\neq 0$, $\\lambda(C)\\leq 1\\iff B(C)/\\tau_{\\mathrm{ind}}\\geq 0\\iff \\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$. Given (a), $\\lambda(C)\\geq 0\\iff B(C)/\\tau_{\\mathrm{ind}}\\leq 1\\iff|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$.\ndocs/paper/appendix_proofs.tex:467:\\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\\lambda_0\\,V_W(C)/(V_W(C)+\\sigma_\\varepsilon^2)$; the rank-one limit $V_W{\\to}V$ yields $\\tau_{\\mathrm{ind}}=\\lambda_0\\,V/(V+\\sigma_\\varepsilon^2)$. Both quantities carry $\\operatorname{sign}(\\lambda_0)$, establishing~(a). The ratio\ndocs/paper/appendix_proofs.tex:473:\\emph{General case.} Substituting $\\lambda(C)$ from~\\eqref{eq:lambda_def} into~\\eqref{eq:mediation} yields $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)=\\lambda(C)\\,\\tau_{\\mathrm{dir}}+(1{-}\\lambda(C))\\,\\tau_{\\mathrm{total}}$, so $\\lambda(C)\\in[0,1]$ iff $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{total}}$.\ndocs/paper/appendix_proofs.tex:475:\\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\\mathbb{E}[T\\mid A^*]=g(A)$, and FWL gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\tau_{\\mathrm{dir}}$, hence $B(I)=0$ and $\\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\\perp A$ so $\\mathbb{E}[T\\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\operatorname{Cov}(Y,T)/\\operatorname{Var}(T)=\\tau_{\\mathrm{total}}$, giving $B=\\tau_{\\mathrm{ind}}$ and $\\lambda=0$.\ndocs/paper/appendix_proofs.tex:479:A natural \\emph{diagnostic} closely related to $\\lambda(C)$ is the between-variance ratio\ndocs/paper/appendix_proofs.tex:484:which satisfies $\\lambda_V(C)\\in[0,1]$ \\emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\\lambda$ and $\\lambda_V$ agree at the endpoints and are related by\ndocs/paper/appendix_proofs.tex:493:\\item \\textbf{Proportional} ($f=\\lambda_0\\,g$, $\\lambda_0\\sim\\mathcal{N}(0,1)\\!\\setminus\\!\\{0\\}$): $\\lambda(C)\\in[0,1]$ in \\emph{all} $30{,}000$ trials (pooled observed range $[1.2{\\times}10^{-5},\\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ therefore reduces to $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\ndocs/paper/appendix_proofs.tex:519:The collider $A$ is a common \\emph{effect} of $T$ and $Y$.\ndocs/paper/appendix_proofs.tex:579:\\emph{Step~1: Bound the numerator.}\ndocs/paper/appendix_proofs.tex:584:\\emph{Step~2: Bound the denominator.}\ndocs/paper/appendix_proofs.tex:587:\\emph{Step~3: Conclude.}\ndocs/paper/appendix_proofs.tex:647:This decomposition reveals that \\emph{misclassification does not affect the confounding component}.\ndocs/paper/appendix_proofs.tex:704:\\emph{Marginal distribution of $A^*$:}\ndocs/paper/appendix_proofs.tex:711:\\emph{Conditional means:}\ndocs/paper/appendix_proofs.tex:724:\\emph{Estimated coefficient:}\ndocs/paper/appendix_proofs.tex:731:\\emph{Mechanism.}\ndocs/paper/appendix_proofs.tex:767:\\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.\ndocs/paper/appendix_proofs.tex:776:Once the condition is satisfied, sign preservation holds for \\emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.\ndocs/paper/appendix_proofs.tex:885:(1)~\\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;\ndocs/paper/appendix_proofs.tex:886:(2)~\\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;\ndocs/paper/appendix_proofs.tex:887:(3)~\\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;\ndocs/paper/appendix_proofs.tex:888:(4)~\\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);\ndocs/paper/appendix_proofs.tex:889:(5)~\\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;\ndocs/paper/appendix_proofs.tex:890:(6)~\\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.\ndocs/paper/appendix_proofs.tex:978:Our taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.\ndocs/paper/appendix_proofs.tex:1018:The non-differential assumption $P(A^*{=}j \\mid A{=}k, Y, \\mathbf{Z}) = P(A^*{=}j \\mid A{=}k)$ holds \\emph{by design} in standard LLM annotation pipelines: the model receives only source text as input and classifies without observing the outcome $Y$ or covariates $\\mathbf{Z}$. The annotation API call is structurally independent of downstream variables, satisfying the conditional independence requirement.\ndocs/paper/appendix_proofs.tex:1059:[Omitted long matching line]\ndocs/paper/appendix_proofs.tex:1163:[Omitted long matching line]\ndocs/paper/appendix_proofs.tex:1429:[Omitted long matching line]\ndocs/paper/introduction.tex:4:[Omitted long matching line]\ndocs/paper/introduction.tex:6:[Omitted long matching line]\ndocs/paper/introduction.tex:20:Counterintuitively, applying corrections without topology awareness can \\emph{worsen} estimates: PPI++ harms M-bias by 88\\% and topology-agnostic IV correction amplifies bias by 139\\%.",
    "numLines": 71
  },
  "sourceToolAssistantUUID": "94f44cd4-3312-455b-a2af-a67bb96bb6a8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 45 · 2026-05-24T06:36:09.139Z_

<details><summary>↩ Tool result · `toolu_01FXZ61p52E6JPgE91ZagcNe`</summary>

```text
docs/paper/e2e_real_cm_table.tex:22:\textit{Median improvement} & & \multicolumn{2}{c}{+93.6\%} & & \multicolumn{2}{c}{-0.0\%} \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c34db5e8-52ec-4909-b7c0-f1c456ba5f89",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "63837d25-d9e1-436a-9500-594a3c8185f7",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/e2e_real_cm_table.tex:22:\\textit{Median improvement} & & \\multicolumn{2}{c}{+93.6\\%} & & \\multicolumn{2}{c}{-0.0\\%} \\\\",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "c34db5e8-52ec-4909-b7c0-f1c456ba5f89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 46 · 2026-05-24T06:36:10.048Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01RQcMYYGYNMQJ6KxHJ3GPZa`</summary>

```json
{
  "pattern": "\\\\emph\\{",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "output_mode": "content",
  "-n": true,
  "glob": "*.tex",
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63837d25-d9e1-436a-9500-594a3c8185f7",
  "isSidechain": false,
  "requestId": "req_011CbLvu9xSVNWZtvN6wcVVm",
  "type": "assistant",
  "uuid": "94f44cd4-3312-455b-a2af-a67bb96bb6a8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRZzeEZuEnpE7J5osqnybi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11815,
      "cache_read_input_tokens": 42867,
      "output_tokens": 1374,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11815,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1374,
          "cache_read_input_tokens": 42867,
          "cache_creation_input_tokens": 11815,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11815
          },
          "type": "message"
        }
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

_source line 47_

```json
{
  "type": "last-prompt",
  "leafUuid": "1e801d34-6875-4c83-b6cf-b5689b65e166",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 48_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 49 · 2026-05-24T06:36:12.192Z_

<details><summary>Logged reasoning block</summary>

```text
Let me now look at the omitted long lines to see their full content.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1e801d34-6875-4c83-b6cf-b5689b65e166",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "a2b4ae14-4edd-4355-bf57-1b94ea815284",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 50 · 2026-05-24T06:36:13.185Z_

Let me read the specific lines that were omitted, and the remaining appendix sections for Part 2.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a2b4ae14-4edd-4355-bf57-1b94ea815284",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "140566db-4689-4398-8baa-f6d7c868429e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-24T06:36:15.079Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KEVwBWWru4Lir52BKvThRb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/related_work.tex",
  "offset": 4,
  "limit": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "140566db-4689-4398-8baa-f6d7c868429e",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "927a1f71-5290-4f5e-9393-fb16e2b30566",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 52 · 2026-05-24T06:36:18.265Z_

<details><summary>↩ Tool result · `toolu_016Dp7tTYFaJSddxMnaEB31i`</summary>

```text
457	Under \emph{proportional effects} ($f(A)=\lambda_0\,g(A)$ with $g(k)=\mathbb{E}[T\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\lambda(C)\in[0,1]$ unconditionally.
458	For \emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[f\mid A^*])$ may differ in sign or magnitude from $\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.
459	The endpoints $\lambda(I)=1$ and $\lambda(C)\to 0$ in the rank-one (uninformative) limit hold in all regimes.
460	
461	\emph{Sign preservation.} When $\lambda(C)\in[0,1]$, the convex-combination form gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)\in[\min(\tau_{\mathrm{dir}},\tau_{\mathrm{total}}),\,\max(\tau_{\mathrm{dir}},\tau_{\mathrm{total}})]$. If additionally $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$, both endpoints share the same sign, so $\operatorname{sign}(\operatorname{plim}\hat\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{dir}})$ for every~$C$. Under proportional effects, $\lambda(C)\in[0,1]$ is automatic (above), so sign preservation of $\hat\tau_{\mathrm{dir}}$ reduces to the single condition $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
462	\end{proposition}
463	
464	\begin{proof}
465	\emph{(a),(b).} With $\tau_{\mathrm{ind}}\neq 0$, $\lambda(C)\leq 1\iff B(C)/\tau_{\mathrm{ind}}\geq 0\iff \operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$. Given (a), $\lambda(C)\geq 0\iff B(C)/\tau_{\mathrm{ind}}\leq 1\iff|B(C)|\leq|\tau_{\mathrm{ind}}|$.
466	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b0b25b5b-e45d-4e4d-81a7-c963b97a1de8",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "3222f3f9-bdff-49cf-a409-e08ed21eb130",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "Under \\emph{proportional effects} ($f(A)=\\lambda_0\\,g(A)$ with $g(k)=\\mathbb{E}[T\\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\\lambda(C)\\in[0,1]$ unconditionally.\nFor \\emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[f\\mid A^*])$ may differ in sign or magnitude from $\\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.\nThe endpoints $\\lambda(I)=1$ and $\\lambda(C)\\to 0$ in the rank-one (uninformative) limit hold in all regimes.\n\n\\emph{Sign preservation.} When $\\lambda(C)\\in[0,1]$, the convex-combination form gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)\\in[\\min(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}}),\\,\\max(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}})]$. If additionally $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$, both endpoints share the same sign, so $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{dir}})$ for every~$C$. Under proportional effects, $\\lambda(C)\\in[0,1]$ is automatic (above), so sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ reduces to the single condition $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\n\\end{proposition}\n\n\\begin{proof}\n\\emph{(a),(b).} With $\\tau_{\\mathrm{ind}}\\neq 0$, $\\lambda(C)\\leq 1\\iff B(C)/\\tau_{\\mathrm{ind}}\\geq 0\\iff \\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$. Given (a), $\\lambda(C)\\geq 0\\iff B(C)/\\tau_{\\mathrm{ind}}\\leq 1\\iff|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$.\n",
      "numLines": 10,
      "startLine": 457,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "b0b25b5b-e45d-4e4d-81a7-c963b97a1de8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 53 · 2026-05-24T06:36:15.085Z_

<details><summary>↩ Tool result · `toolu_01KEVwBWWru4Lir52BKvThRb`</summary>

```text
4	\paragraph{Measurement error in causal inference.}
5	Foundations appear in \citet{carroll2006, gustafson2004, buonaccorsi2010, bound2001measurement}, with DAG-based formalization by \citet{hernan_cole2009} and \citet{kuroki_pearl2014}. For binary variables, non-differential misclassification biases toward the null~\cite{bross1954misclassification, brenner1993, ogburn_vanderweele2012}, but this fails for polytomous exposures~\cite{dosemeci1990, jurek2005, veirod_laake2001}. Extensions address differential measurement error~\cite{edwards_lessler_naimi2021, imai_yamamoto2010}, endogenous misreporting~\cite{nguimkeu_denteh_tchernis2019}, mismeasured covariates under IPW~\cite{shu_yi2019a, shu_yi2019b}, mediation with mismeasured mediators~\cite{valeri_vanderweele2013}, nonclassical error~\cite{schennach2020mismeasured}, and multiply robust estimation~\cite{wei2025multiply}. All analyze a single DAG topology; ours characterizes how the \emph{same} confusion matrix produces qualitatively different bias across seven topologies.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "927a1f71-5290-4f5e-9393-fb16e2b30566",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "3de1976d-1cbd-4ffc-9ecd-86897dd0b347",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/related_work.tex",
      "content": "\\paragraph{Measurement error in causal inference.}\nFoundations appear in \\citet{carroll2006, gustafson2004, buonaccorsi2010, bound2001measurement}, with DAG-based formalization by \\citet{hernan_cole2009} and \\citet{kuroki_pearl2014}. For binary variables, non-differential misclassification biases toward the null~\\cite{bross1954misclassification, brenner1993, ogburn_vanderweele2012}, but this fails for polytomous exposures~\\cite{dosemeci1990, jurek2005, veirod_laake2001}. Extensions address differential measurement error~\\cite{edwards_lessler_naimi2021, imai_yamamoto2010}, endogenous misreporting~\\cite{nguimkeu_denteh_tchernis2019}, mismeasured covariates under IPW~\\cite{shu_yi2019a, shu_yi2019b}, mediation with mismeasured mediators~\\cite{valeri_vanderweele2013}, nonclassical error~\\cite{schennach2020mismeasured}, and multiply robust estimation~\\cite{wei2025multiply}. All analyze a single DAG topology; ours characterizes how the \\emph{same} confusion matrix produces qualitatively different bias across seven topologies.",
      "numLines": 2,
      "startLine": 4,
      "totalLines": 12
    }
  },
  "sourceToolAssistantUUID": "927a1f71-5290-4f5e-9393-fb16e2b30566",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-24T06:36:16.055Z_

<details open><summary>🔧 Tool call — Read · `toolu_014YF8DftHPsM48LgR8QvzWM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 1055,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3de1976d-1cbd-4ffc-9ecd-86897dd0b347",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "d76ebd2c-25bf-4c45-8682-9604628eb8d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 55 · 2026-05-24T06:36:16.060Z_

<details><summary>↩ Tool result · `toolu_014YF8DftHPsM48LgR8QvzWM`</summary>

```text
1055	
1056	\input{exp_a_stress_test_table.tex}
1057	
1058	\paragraph{Structured violation models.}
1059	Beyond uniform perturbations, we compare two structured violation models across all seven topologies ($K{=}3$, 1{,}000 matrices per $\varepsilon$, $\min_k C_{kk}{\geq}0.7$): (1)~\emph{outcome-conditional}, where $\tilde{C}$ applies to $Y{>}\text{median}(Y)$ while $C_0$ applies below; (2)~\emph{label-specific}, where off-diagonal perturbation magnitude scales with $|\text{corr}(A{=}k, Y)|$, modeling accuracy degradation on $Y$-predictive categories. For exposure at $\varepsilon{=}0.20$, label-specific violations are substantially milder than uniform (sign-flip 0.1\% vs.\ 10.1\%), while outcome-conditional violations are more severe (sign-flip 13.9\%, mean relative bias 0.50 vs.\ 0.40). All five sign-preserving topologies maintain 0\% sign-flip under both structured models at all $\varepsilon$ tested; IV likewise shows 0\% sign-flip (its vulnerability requires pathological diagonal structure, not differential error). These results indicate that the uniform perturbation model is neither uniformly conservative nor uniformly liberal: practitioners should assess which violation pattern is most plausible for their annotation pipeline.
1060	
1061	\subsection{Robustness to Nonlinear DGP}
1062	\label{sec:logistic_dgp}
1063	
1064	We replace the linear structural equations with $Y \sim \text{Bernoulli}(\sigma(\mathbf{x}^\top\boldsymbol{\beta}))$ and estimate via logistic regression (control function for IV) for all seven topologies, using $K{=}3$, six real VAST confusion matrices, 500 MC replications, and $N{=}10{,}000$. Mean sign-flip rates across the six CMs:
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d76ebd2c-25bf-4c45-8682-9604628eb8d4",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "4ef97b5d-57b1-4e99-bf38-0df477b34055",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\n\\input{exp_a_stress_test_table.tex}\n\n\\paragraph{Structured violation models.}\nBeyond uniform perturbations, we compare two structured violation models across all seven topologies ($K{=}3$, 1{,}000 matrices per $\\varepsilon$, $\\min_k C_{kk}{\\geq}0.7$): (1)~\\emph{outcome-conditional}, where $\\tilde{C}$ applies to $Y{>}\\text{median}(Y)$ while $C_0$ applies below; (2)~\\emph{label-specific}, where off-diagonal perturbation magnitude scales with $|\\text{corr}(A{=}k, Y)|$, modeling accuracy degradation on $Y$-predictive categories. For exposure at $\\varepsilon{=}0.20$, label-specific violations are substantially milder than uniform (sign-flip 0.1\\% vs.\\ 10.1\\%), while outcome-conditional violations are more severe (sign-flip 13.9\\%, mean relative bias 0.50 vs.\\ 0.40). All five sign-preserving topologies maintain 0\\% sign-flip under both structured models at all $\\varepsilon$ tested; IV likewise shows 0\\% sign-flip (its vulnerability requires pathological diagonal structure, not differential error). These results indicate that the uniform perturbation model is neither uniformly conservative nor uniformly liberal: practitioners should assess which violation pattern is most plausible for their annotation pipeline.\n\n\\subsection{Robustness to Nonlinear DGP}\n\\label{sec:logistic_dgp}\n\nWe replace the linear structural equations with $Y \\sim \\text{Bernoulli}(\\sigma(\\mathbf{x}^\\top\\boldsymbol{\\beta}))$ and estimate via logistic regression (control function for IV) for all seven topologies, using $K{=}3$, six real VAST confusion matrices, 500 MC replications, and $N{=}10{,}000$. Mean sign-flip rates across the six CMs:",
      "numLines": 10,
      "startLine": 1055,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "d76ebd2c-25bf-4c45-8682-9604628eb8d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 56 · 2026-05-24T06:36:16.969Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FKLBE19BiwCa5gk23rCemD`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 1159,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4ef97b5d-57b1-4e99-bf38-0df477b34055",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "28a615b9-13c8-497a-bd0a-f08fc216a94b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-24T06:36:16.975Z_

<details><summary>↩ Tool result · `toolu_01FKLBE19BiwCa5gk23rCemD`</summary>

```text
1159	
1160	Violation counts are high (60--97\% of matrices), but magnitudes are small for non-IV topologies under the default parameterization (Table~\ref{tab:conjecture_verify}); DGP sensitivity analysis (Table~\ref{tab:dgp_sensitivity}) shows $\varepsilon$ scales with effect magnitude $|\beta|$, remaining below 0.02 for $|\beta| \leq 1$ across non-exposure topologies. These results are computed from analytic probability limits with zero sampling noise, confirming the violations are structural properties of multi-class confusion matrices rather than numerical artifacts. IV deviations reflect Wald estimator singularities when the first-stage coefficient passes near zero---this is a property of the Wald estimator, not of the ASV parameterization. Adversarial search (500 restarts per configuration, $K \in \{3,5\}$) finds genuine counterexamples for all topologies except IV $K{=}3$, confirming that strict monotonicity does not hold universally. The bias envelope is $\varepsilon$-approximately monotonic with $\varepsilon < 0.03$ for collider and M-bias across all tested $\tau$; confounding, mediation, and front-door achieve $\varepsilon < 0.06$ at default DGP parameters (see DGP sensitivity below); exposure satisfies $\varepsilon_{p99} < 0.008$ but extreme-tail matrices ($<$0.02\% of draws) reach $\varepsilon \approx 0.15$. Empirically, $\varepsilon$ scales as $O(1/K^\alpha)$ with $\alpha \in [0.6, 1.5]$ (topology-dependent): for confounding, mediation, and front-door, $\alpha \approx 1.4$; for exposure, $\alpha \approx 1.0$; for collider and M-bias, $\alpha \approx 0.7$. A universal empirical upper bound is $\varepsilon \leq 0.137/\sqrt{K}$, verified across all tested configurations ($K \in \{3,5,7\}$). This scaling supports the practical validity of ASV as a sensitivity tool at any meaningful bias threshold.
1161	
1162	\paragraph{DGP parameter sensitivity.}
1163	We repeat the verification across $\tau \in \{0.1, 0.5, 1.0, 2.0, 5.0\}$, varying the direct $T{\to}Y$ coefficient for confounding ($\beta_T{=}\tau$), mediation, collider, and M-bias (DGP $\tau$), and rescaling the $A{\to}Y$ coefficient vector to $\boldsymbol{\beta}\cdot\tau$ for exposure and front-door. With 10{,}000 random $C_0$ per $(K,\tau)$ setting (Table~\ref{tab:conjecture_tau_sens}), $\varepsilon$ remains small ($< 0.03$) for $\tau \geq 0.5$ for confounding, mediation, collider, and M-bias, but grows at $\tau{=}0.1$: mediation produces 1{,}950 / 30{,}000 violations across $K \in \{3,5,7\}$ (worst $\varepsilon{=}0.130$ at $K{=}3$) and confounding 200 / 30{,}000 (worst $\varepsilon{=}0.118$ at $K{=}3$). The mechanism is dimensional: additive terms not scaling with $\tau$ (e.g.\ the $\boldsymbol{\beta}$-contribution to $\mathbb{E}[Y D_k]$ in mediation and confounding) contribute a $\tau$-independent offset to the bias numerator, so the ratio $|B|/|\tau|$ inflates as $\tau \to 0$. A single mediation violation at $\tau{=}2.0$ ($\varepsilon{=}0.112$, 1/30{,}000 matrices) arises from a specific confusion matrix structure where off-diagonal entries induce partial cancellation along the mediation pathway; this isolated case does not affect the $p_{99}$ bound ($\varepsilon_{p99}{=}0.005$). Collider and M-bias remain robust at all $\tau$ ($\varepsilon{<}0.022$ and $\varepsilon{<}0.015$ respectively). Exposure shows scattered tail outliers but $\overline{\varepsilon} \approx 3\!\times\!10^{-4}$ at every $\tau$, consistent with linear scaling: when $\boldsymbol{\beta}$ rescales by $\tau$, both bias and $\tau_{\text{true}}$ scale by the same factor and $\varepsilon$ is theoretically invariant. Front-door inverts the pattern ($\varepsilon$ \emph{grows} with $\tau$, reaching $0.139$ at $\tau{=}5$, $K{=}3$, with 664 violations) because $\tau_{\text{true}} = \operatorname{plim}(\hat{\tau}_T \mid C{=}I)$ is pinned at $0.5$ by the $U$-confounding path while bias magnitudes scale with $\boldsymbol{\beta}$---this is an artefact of how $\tau_{\text{true}}$ is normalised, not a genuine failure of envelope monotonicity. In practice, ASV's $\delta^*$ thresholds (typically $\geq 0.1$ in our deployment) are well above the region where these $\varepsilon$-violations occur, so the small-$\tau$ degradation does not affect ASV's operational reliability; we flag it as a caveat for applications targeting $|\tau| \lesssim 0.1$ in standardised units.
1164	
1165	\begin{table}[h]
1166	\centering
1167	\small
1168	\caption{$\varepsilon \equiv \max_\delta(|B(\delta{+}\Delta)|{-}|B(\delta)|)/|\tau_{\text{true}}|$ in the non-monotonic direction (max over $K \in \{3,5,7\}$; 10{,}000 random $C_0$ per cell). Bold marks $\varepsilon > 0.02$ (non-exposure) or $\varepsilon > 0.08$ (exposure). Counts in parentheses are violations / 30{,}000. Tables~\ref{tab:conjecture_verify} and~\ref{tab:conjecture_tau_sens} use independent random seeds; for topologies with low violation rates (exposure $<$0.02\%), the worst-case $\varepsilon$ is sample-sensitive.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "28a615b9-13c8-497a-bd0a-f08fc216a94b",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "7651ed4b-15d6-4735-be21-bfde2b2177a2",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\nViolation counts are high (60--97\\% of matrices), but magnitudes are small for non-IV topologies under the default parameterization (Table~\\ref{tab:conjecture_verify}); DGP sensitivity analysis (Table~\\ref{tab:dgp_sensitivity}) shows $\\varepsilon$ scales with effect magnitude $|\\beta|$, remaining below 0.02 for $|\\beta| \\leq 1$ across non-exposure topologies. These results are computed from analytic probability limits with zero sampling noise, confirming the violations are structural properties of multi-class confusion matrices rather than numerical artifacts. IV deviations reflect Wald estimator singularities when the first-stage coefficient passes near zero---this is a property of the Wald estimator, not of the ASV parameterization. Adversarial search (500 restarts per configuration, $K \\in \\{3,5\\}$) finds genuine counterexamples for all topologies except IV $K{=}3$, confirming that strict monotonicity does not hold universally. The bias envelope is $\\varepsilon$-approximately monotonic with $\\varepsilon < 0.03$ for collider and M-bias across all tested $\\tau$; confounding, mediation, and front-door achieve $\\varepsilon < 0.06$ at default DGP parameters (see DGP sensitivity below); exposure satisfies $\\varepsilon_{p99} < 0.008$ but extreme-tail matrices ($<$0.02\\% of draws) reach $\\varepsilon \\approx 0.15$. Empirically, $\\varepsilon$ scales as $O(1/K^\\alpha)$ with $\\alpha \\in [0.6, 1.5]$ (topology-dependent): for confounding, mediation, and front-door, $\\alpha \\approx 1.4$; for exposure, $\\alpha \\approx 1.0$; for collider and M-bias, $\\alpha \\approx 0.7$. A universal empirical upper bound is $\\varepsilon \\leq 0.137/\\sqrt{K}$, verified across all tested configurations ($K \\in \\{3,5,7\\}$). This scaling supports the practical validity of ASV as a sensitivity tool at any meaningful bias threshold.\n\n\\paragraph{DGP parameter sensitivity.}\nWe repeat the verification across $\\tau \\in \\{0.1, 0.5, 1.0, 2.0, 5.0\\}$, varying the direct $T{\\to}Y$ coefficient for confounding ($\\beta_T{=}\\tau$), mediation, collider, and M-bias (DGP $\\tau$), and rescaling the $A{\\to}Y$ coefficient vector to $\\boldsymbol{\\beta}\\cdot\\tau$ for exposure and front-door. With 10{,}000 random $C_0$ per $(K,\\tau)$ setting (Table~\\ref{tab:conjecture_tau_sens}), $\\varepsilon$ remains small ($< 0.03$) for $\\tau \\geq 0.5$ for confounding, mediation, collider, and M-bias, but grows at $\\tau{=}0.1$: mediation produces 1{,}950 / 30{,}000 violations across $K \\in \\{3,5,7\\}$ (worst $\\varepsilon{=}0.130$ at $K{=}3$) and confounding 200 / 30{,}000 (worst $\\varepsilon{=}0.118$ at $K{=}3$). The mechanism is dimensional: additive terms not scaling with $\\tau$ (e.g.\\ the $\\boldsymbol{\\beta}$-contribution to $\\mathbb{E}[Y D_k]$ in mediation and confounding) contribute a $\\tau$-independent offset to the bias numerator, so the ratio $|B|/|\\tau|$ inflates as $\\tau \\to 0$. A single mediation violation at $\\tau{=}2.0$ ($\\varepsilon{=}0.112$, 1/30{,}000 matrices) arises from a specific confusion matrix structure where off-diagonal entries induce partial cancellation along the mediation pathway; this isolated case does not affect the $p_{99}$ bound ($\\varepsilon_{p99}{=}0.005$). Collider and M-bias remain robust at all $\\tau$ ($\\varepsilon{<}0.022$ and $\\varepsilon{<}0.015$ respectively). Exposure shows scattered tail outliers but $\\overline{\\varepsilon} \\approx 3\\!\\times\\!10^{-4}$ at every $\\tau$, consistent with linear scaling: when $\\boldsymbol{\\beta}$ rescales by $\\tau$, both bias and $\\tau_{\\text{true}}$ scale by the same factor and $\\varepsilon$ is theoretically invariant. Front-door inverts the pattern ($\\varepsilon$ \\emph{grows} with $\\tau$, reaching $0.139$ at $\\tau{=}5$, $K{=}3$, with 664 violations) because $\\tau_{\\text{true}} = \\operatorname{plim}(\\hat{\\tau}_T \\mid C{=}I)$ is pinned at $0.5$ by the $U$-confounding path while bias magnitudes scale with $\\boldsymbol{\\beta}$---this is an artefact of how $\\tau_{\\text{true}}$ is normalised, not a genuine failure of envelope monotonicity. In practice, ASV's $\\delta^*$ thresholds (typically $\\geq 0.1$ in our deployment) are well above the region where these $\\varepsilon$-violations occur, so the small-$\\tau$ degradation does not affect ASV's operational reliability; we flag it as a caveat for applications targeting $|\\tau| \\lesssim 0.1$ in standardised units.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{$\\varepsilon \\equiv \\max_\\delta(|B(\\delta{+}\\Delta)|{-}|B(\\delta)|)/|\\tau_{\\text{true}}|$ in the non-monotonic direction (max over $K \\in \\{3,5,7\\}$; 10{,}000 random $C_0$ per cell). Bold marks $\\varepsilon > 0.02$ (non-exposure) or $\\varepsilon > 0.08$ (exposure). Counts in parentheses are violations / 30{,}000. Tables~\\ref{tab:conjecture_verify} and~\\ref{tab:conjecture_tau_sens} use independent random seeds; for topologies with low violation rates (exposure $<$0.02\\%), the worst-case $\\varepsilon$ is sample-sensitive.}",
      "numLines": 10,
      "startLine": 1159,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "28a615b9-13c8-497a-bd0a-f08fc216a94b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 58 · 2026-05-24T06:36:17.651Z_

<details open><summary>🔧 Tool call — Read · `toolu_014Z8hC1FNLZ3JrDARyARr55`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 1425,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7651ed4b-15d6-4735-be21-bfde2b2177a2",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "01445a28-1ef1-424b-9dd5-473568c60cd6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 59 · 2026-05-24T06:36:17.655Z_

<details><summary>↩ Tool result · `toolu_014Z8hC1FNLZ3JrDARyARr55`</summary>

```text
1425	\bottomrule
1426	\end{tabular}
1427	\end{table}
1428	
1429	Five topologies show the expected negative correlation: better annotation quality ($F_1{\uparrow}$) reduces causal bias. IV shows the strongest effect ($\rho = -0.70$), consistent with the Wald estimator's sensitivity to misclassification in the first stage. M-bias uniquely reverses: $\rho = +0.87$ ($p < 0.001$). The mechanism is that misclassification attenuates the spurious M-bias path, so the naive estimator under noisy annotations is \emph{closer} to the true causal effect; improving annotation quality (higher $F_1$) removes this protective attenuation and \emph{increases} bias. This is consistent with the correction results (\S\ref{sec:correction}), where PPI++ harms M-bias ($-$88\%) by removing the same protective noise. Collider shows a positive but non-significant trend ($\rho = +0.31$, $p = 0.15$), consistent with Berkson bias attenuation. Per-dataset breakdowns (CivilComments $K{=}2$: $\rho = -1.0$ for all topologies with $n{=}7$) should be interpreted with caution given the small sample and limited $F_1$ variation within the binary task.
1430	
1431	\subsection{Confusion Matrix Estimation Robustness}
1432	\label{sec:c_robustness}
1433	
1434	The ASV framework requires the confusion matrix $C$, which in practice must be estimated from a held-out gold-labeled subset. We assess how estimation noise in $\hat{C}$ propagates to the safe/fragile partition and ASV ranking. For each of 8 empirical confusion matrices (VAST, 4 LLMs $\times$ 2 prompting strategies), we draw $n_{\text{gold}} \in \{50, 100, 200, 500\}$ samples from a $\text{Multinomial}(n_{\text{gold}}, C_{\cdot k})$ distribution per column, compute $\hat{C}$, and evaluate the resulting ASV ranking across 200 bootstrap replicates.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "01445a28-1ef1-424b-9dd5-473568c60cd6",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "6b0d549e-7a11-4e0a-a937-3051cd93ccf7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFive topologies show the expected negative correlation: better annotation quality ($F_1{\\uparrow}$) reduces causal bias. IV shows the strongest effect ($\\rho = -0.70$), consistent with the Wald estimator's sensitivity to misclassification in the first stage. M-bias uniquely reverses: $\\rho = +0.87$ ($p < 0.001$). The mechanism is that misclassification attenuates the spurious M-bias path, so the naive estimator under noisy annotations is \\emph{closer} to the true causal effect; improving annotation quality (higher $F_1$) removes this protective attenuation and \\emph{increases} bias. This is consistent with the correction results (\\S\\ref{sec:correction}), where PPI++ harms M-bias ($-$88\\%) by removing the same protective noise. Collider shows a positive but non-significant trend ($\\rho = +0.31$, $p = 0.15$), consistent with Berkson bias attenuation. Per-dataset breakdowns (CivilComments $K{=}2$: $\\rho = -1.0$ for all topologies with $n{=}7$) should be interpreted with caution given the small sample and limited $F_1$ variation within the binary task.\n\n\\subsection{Confusion Matrix Estimation Robustness}\n\\label{sec:c_robustness}\n\nThe ASV framework requires the confusion matrix $C$, which in practice must be estimated from a held-out gold-labeled subset. We assess how estimation noise in $\\hat{C}$ propagates to the safe/fragile partition and ASV ranking. For each of 8 empirical confusion matrices (VAST, 4 LLMs $\\times$ 2 prompting strategies), we draw $n_{\\text{gold}} \\in \\{50, 100, 200, 500\\}$ samples from a $\\text{Multinomial}(n_{\\text{gold}}, C_{\\cdot k})$ distribution per column, compute $\\hat{C}$, and evaluate the resulting ASV ranking across 200 bootstrap replicates.",
      "numLines": 10,
      "startLine": 1425,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "01445a28-1ef1-424b-9dd5-473568c60cd6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 60 · 2026-05-24T06:36:18.261Z_

<details open><summary>🔧 Tool call — Read · `toolu_016Dp7tTYFaJSddxMnaEB31i`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 457,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6b0d549e-7a11-4e0a-a937-3051cd93ccf7",
  "isSidechain": false,
  "requestId": "req_011CbLvwHyhR3XDe1rbpRvUZ",
  "type": "assistant",
  "uuid": "b0b25b5b-e45d-4e4d-81a7-c963b97a1de8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vn3vxFk4Ph7ncjPocQYf5s",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5376,
      "cache_read_input_tokens": 54682,
      "output_tokens": 617,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5376,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 617,
          "cache_read_input_tokens": 54682,
          "cache_creation_input_tokens": 5376,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5376
          },
          "type": "message"
        }
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

_source line 61 · 2026-05-24T06:36:18.330Z_

```json
{
  "parentUuid": "3222f3f9-bdff-49cf-a409-e08ed21eb130",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "014143de-90ff-4fed-b225-3778c7128568",
  "timestamp": "2026-05-24T06:36:18.330Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 62_

```json
{
  "type": "last-prompt",
  "leafUuid": "014143de-90ff-4fed-b225-3778c7128568",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 63_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 64 · 2026-05-24T06:37:13.712Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me collect all the labeled equations in the main text (method.tex and experiments.tex) and then check appendix_proofs.tex for duplicates.

Let me first get a complete picture of the italic usage issues. Let me categorize all \emph{} and \textit{} uses:

**Legitimate uses (keep):**
1. `\emph{structure}` (intro:4) — genuine emphasis contrasting "structure" vs "magnitude"
2. `\emph{vanishes}` (intro:6) — genuine emphasis on key result
3. `\emph{worsen}` (intro:20) — genuine emphasis on counterintuitive finding


4. `\emph{starred-node}` (method:7) — first definition of technical term
5. `\emph{linear}` (method:21) — emphasizing scope limitation
6. `\emph{sign reversal}` (method:42) — this reappears without italic in the intro, but here it's being formally defined as the central phenomenon for this topology, so the emphasis serves a structural purpose even if it's a second mention.
7. `\emph{protective}` and `\emph{immune}` (method:64) — introducing these terms in the taxonomy
8. `\emph{(a)}`, `\emph{(b)}`, `\emph{(c)}` (method:73-75) — standard proposition labeling
9. `\emph{same}` (related_work:5) — emphasizing that the same confusion matrix yields different results, which is the core contribution
10. All proof step headers across the proof files — standard academic formatting
11. `\emph{stronger}` (k3:116) — genuine emphasis in a comparison
12. `\emph{all}` (appendix:183, 226, 776) — logical emphasis in mathematical statements, particularly in universal quantifiers like "for all column-stochastic C"
13. `\emph{causes}` (appendix:336) — highlighting the distinction in causal direction
14. `\emph{conditional indirect effect}` (appendix:373) — first definition of this term
15. `\emph{constant}` (appendix:424) — mathematical emphasis on a key insight
16. `\emph{implicitly}` (appendix:438) — mathematical emphasis
17. `\emph{proportional effects}` (appendix:457) — checking whether this is the first definition in the appendix, since the term appears earlier in method.tex without italics around line 95-99

. This turns out to be redundant re-emphasis since it's already been defined in the main text.
18. `\emph{general (non-proportional)}` (appendix:458) — standard case labeling
19. `\emph{diagnostic}` (appendix:479) — introducing a new term legitimately
20. `\emph{unconditionally}` (appendix:484) — mathematical emphasis, removable but standard
21. `\emph{all}` (appendix:493) — emphasizing the full set of 30,000 trials
22. `\emph{effect}` (appendix:519) — legitimate emphasis on the causal role in "common effect"
23. `\emph{misclassification does` — continuing to evaluate the next italicized term

Continuing through the remaining instances: the key result that misclassification doesn't affect the confounding component gets legitimate emphasis, proof section headers like "Marginal distribution" and "Conditional means" follow standard formatting conventions, "M-bias" labels a topology in a list, "confounding topology" appears to be unnecessary re-emphasis since it's already heavily used throughout, "by design" genuinely emphasizes an architectural guarantee, and the final pair "outcome-conditional" and "label-specific" represent first definitions of violations.

Moving into the next batch, counterintuitive results like "closer" and "increases" warrant emphasis, directional language like "grows" is legitimately highlighted, "component-wise diagonal dominance" is a first definition so it's appropriate, and the confusion matrix configurations are just standard enumerated item labels. For `\textit{}`, the "Median improvement" italicization in the table is actually fine since italicizing summary rows is conventional formatting.

Now I need to identify which instances are genuinely problematic.  "Confounding topology" appears throughout the paper without italics, so this isn't a first definition and should be removed. "Proportional effects" is already defined elsewhere, so that emphasis is redundant. The "general (non-proportional)" case label is borderline—it's distinguishing between two regimes, which could justify the italics. "Sign reversal" was mentioned earlier without italics in the introduction, so this one shouldn't be emphasized either.

Actually, looking more closely at the method section, this is where "sign reversal" gets its formal explanation as a mechanism, which makes it the definitional context. I'll keep that one. But I need to verify whether "proportional effects" is actually introduced as a defined term in method.tex or just used casually—checking line 92 where it appears in the context of a mathematical condition.

Now I'm going through the appendix more systematically to identify which emphasis uses are actually problematic. Most of the \emph uses in the proofs section follow standard mathematical writing conventions, and legitimate emphasis on words like "all," "causes," and "stronger" serves a real purpose. Let me continue examining what's actually worth changing. I should systematically go through the remaining appendix sections to check for any other problematic italic usage.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "014143de-90ff-4fed-b225-3778c7128568",
  "isSidechain": false,
  "requestId": "req_011CbLvwvQgvQBtz9tpEKbR1",
  "type": "assistant",
  "uuid": "6379c181-159a-4532-8c57-9faf63916542",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AKVMaUPAMGdh4mPtfBLzZa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4664,
      "cache_read_input_tokens": 60058,
      "output_tokens": 2599,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4664,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2599,
          "cache_read_input_tokens": 60058,
          "cache_creation_input_tokens": 4664,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4664
          },
          "type": "message"
        }
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

_source line 65 · 2026-05-24T06:37:13.797Z_

Let me read more of the appendix to check for formula duplication and remaining italic issues.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6379c181-159a-4532-8c57-9faf63916542",
  "isSidechain": false,
  "requestId": "req_011CbLvwvQgvQBtz9tpEKbR1",
  "type": "assistant",
  "uuid": "a352d4c9-9d4d-4dfb-9d0f-3854d3f8c648",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AKVMaUPAMGdh4mPtfBLzZa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4664,
      "cache_read_input_tokens": 60058,
      "output_tokens": 2599,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4664,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2599,
          "cache_read_input_tokens": 60058,
          "cache_creation_input_tokens": 4664,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4664
          },
          "type": "message"
        }
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

_source line 66 · 2026-05-24T06:37:15.816Z_

<details open><summary>🔧 Tool call — Read · `toolu_017BBzdVY2LHfiTDVGefvvNF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 200,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a352d4c9-9d4d-4dfb-9d0f-3854d3f8c648",
  "isSidechain": false,
  "requestId": "req_011CbLvwvQgvQBtz9tpEKbR1",
  "type": "assistant",
  "uuid": "cecb6751-e2a6-49fa-8165-30566fe642e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AKVMaUPAMGdh4mPtfBLzZa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4664,
      "cache_read_input_tokens": 60058,
      "output_tokens": 2599,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4664,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2599,
          "cache_read_input_tokens": 60058,
          "cache_creation_input_tokens": 4664,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4664
          },
          "type": "message"
        }
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

_source line 67 · 2026-05-24T06:37:17.364Z_

<details><summary>↩ Tool result · `toolu_01P5ev9KR6Wx7k9Fs277t5AR`</summary>

```text
550	\label{prop:col_prop}
551	If $h(A)=\lambda\,g(A)$ for some constant $\lambda$, then $|B(C)|\leq|B(I)|$ for all column-stochastic $C$, and $B(C)$ has the same sign as $B(I)$.
552	Consequently, $\operatorname{sign}(\operatorname{plim}\hat\tau)=\operatorname{sign}(\tau)$ whenever $\operatorname{sign}(\tau)=\operatorname{sign}(\tau+B_{\mathrm{Berkson}})$.
553	\end{proposition}
554	
555	\begin{proof}
556	When $h=\lambda g$, the numerator becomes $-\lambda\,\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])$ and the denominator is $\operatorname{Var}(T)-\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])$.
557	Let $V^*=\operatorname{Var}(\mathbb{E}[g(A)\mid A^*])\in[0,V_g]$ where $V_g=\operatorname{Var}(g(A))$.
558	Then
559	\[
560	  |B(C)| = |\lambda|\,\frac{V^*}{\operatorname{Var}(T)-V^*}.
561	\]
562	The function $x\mapsto x/(a-x)$ is increasing on $[0,a)$.
563	With $a=\operatorname{Var}(T)>V_g\geq V^*$:
564	$|B(C)|\leq|\lambda|\,V_g/(\operatorname{Var}(T)-V_g)=|B(I)|$.
565	At $V^*{=}0$ (uniform $C$): $B{=}0$.  At $V^*{=}V_g$ ($C{=}I$): $B{=}B(I)$.
566	\end{proof}
567	
568	\begin{proposition}[Collider sign preservation --- general case]
569	\label{prop:col_gen}
570	Define
571	\begin{equation}
572	  \bar{B}_{\mathrm{col}} = \frac{\sqrt{\operatorname{Var}(g(A))\,\operatorname{Var}(h(A))}}{\mathbb{E}[\operatorname{Var}(T\mid A)]}.
573	  \label{eq:bbar_col}
574	\end{equation}
575	If $|\tau|>\bar{B}_{\mathrm{col}}$, then $\operatorname{sign}(\operatorname{plim}\hat\tau(C))=\operatorname{sign}(\tau)$ for all column-stochastic $C$.
576	\end{proposition}
577	
578	\begin{proof}
579	\emph{Step~1: Bound the numerator.}
580	By Cauchy--Schwarz:
581	$|\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[h\mid A^*])|\leq\sqrt{\operatorname{Var}(\mathbb{E}[g\mid A^*])\,\operatorname{Var}(\mathbb{E}[h\mid A^*])}$.
582	Since conditional expectation reduces variance: $\operatorname{Var}(\mathbb{E}[g\mid A^*])\leq\operatorname{Var}(g(A))$ and likewise for $h$.
583	
584	\emph{Step~2: Bound the denominator.}
585	$\mathbb{E}[\operatorname{Var}(T\mid A^*)]=\operatorname{Var}(T)-\operatorname{Var}(\mathbb{E}[T\mid A^*])\geq\operatorname{Var}(T)-\operatorname{Var}(g(A))=\mathbb{E}[\operatorname{Var}(T\mid A)]$.
586	
587	\emph{Step~3: Conclude.}
588	$|B(C)|\leq\sqrt{\operatorname{Var}(g)\,\operatorname{Var}(h)}\,/\,\mathbb{E}[\operatorname{Var}(T\mid A)]=\bar{B}_{\mathrm{col}}$.
589	When $|\tau|>\bar{B}_{\mathrm{col}}$, the bias cannot overwhelm $\tau$. In practice, $\operatorname{Var}(g(A))$ and $\operatorname{Var}(h(A))$ can be estimated from observable data by bootstrapping regression coefficients from $A^*$-stratified subsamples, yielding conservative upper bounds on $\bar{B}_{\mathrm{col}}$.
590	\end{proof}
591	
592	\paragraph{Verification for paper parameters ($K{=}3$).}
593	With $\tau{=}1.0$, $\boldsymbol{\delta}_T{=}(0,\,0.5,\,{-}0.3)$, $\boldsymbol{\delta}_Y{=}(0,\,0.8,\,0.6)$, from $5{\times}10^6$-sample Monte Carlo:
594	\begin{align*}
595	  \operatorname{Var}(g(A)) &= 0.187,\quad
596	  \operatorname{Var}(h(A)) = 0.076,\quad
597	  \mathbb{E}[\operatorname{Var}(T\mid A)] = 0.813,\\
598	  \bar{B}_{\mathrm{col}} &= \sqrt{0.187\times 0.076}\;/\;0.813 = 0.147.
599	\end{align*}
600	Since $|\tau|{=}1.0\gg\bar{B}_{\mathrm{col}}{=}0.147$, Proposition~\ref{prop:col_gen} guarantees sign preservation.
601	Additionally, $B_{\mathrm{Berkson}}{=}{-}0.114$, giving $\tau+B_{\mathrm{Berkson}}{=}0.886{>}0$.
602	Verified across $100{,}000$ random column-stochastic $C$: $\tau_{\mathrm{sign\,flip}}{=}0\%$, and $|B(C)|\leq|B_{\mathrm{Berkson}}|$ in all cases.
603	
604	\subsection{Front-door Topology ($A$ = Mediator under Confounding)}
605	\label{app:frontdoor}
606	
607	\paragraph{Data-generating process.}
608	$T\to A\to Y$, $U\to T$, $U\to Y$.
609	An unobserved confounder $U$ affects both treatment and outcome:
610	\begin{align*}
611	  U &\sim \mathcal{N}(0,1),\quad
612	  T = \alpha_U\,U + \eta,\quad \eta\sim\mathcal{N}(0,1),\;\eta\perp U,\\
613	  A\mid T &\sim \operatorname{Categorical}\bigl(\operatorname{softmax}(\boldsymbol{\gamma}+\boldsymbol{\delta}\,T)\bigr),\\
614	  Y &= f(A) + \lambda\,U + \varepsilon_Y,\quad \varepsilon_Y\perp(T,A,U).
615	\end{align*}
616	There is no direct $T{\to}Y$ edge; the causal effect of $T$ on $Y$ operates entirely through $A$.
617	The researcher controls for $A^*$ in $Y\sim 1+T+D_1^*+\cdots+D_{K-1}^*$.
618	
619	\paragraph{Bias decomposition.}
620	Since the direct effect is zero, the FWL coefficient on $T$ captures only bias:
621	\[
622	  \operatorname{plim}\hat\tau(C) = \frac{\mathbb{E}[\operatorname{Cov}(T,\,Y\mid A^*)]}{\mathbb{E}[\operatorname{Var}(T\mid A^*)]}.
623	\]
624	Substituting $Y=f(A)+\lambda U+\varepsilon_Y$ and using $\varepsilon_Y\perp(T,A,A^*)$:
625	\begin{equation}
626	  \operatorname{plim}\hat\tau(C)
627	  = \underbrace{\frac{\lambda\,\alpha_U}{\operatorname{Var}(T)}}_{\text{confounding (constant)}}
628	  \;+\; \underbrace{\frac{\mathbb{E}[\operatorname{Cov}(T,\,f(A)\mid A^*)]}{D(C)}}_{\displaystyle B_{\mathrm{med}}(C)},
629	  \label{eq:fd_decomp}
630	\end{equation}
631	where $D(C)=\mathbb{E}[\operatorname{Var}(T\mid A^*)]$.
632	
633	\begin{proof}[Derivation of~\eqref{eq:fd_decomp}]
634	Expand the numerator as
635	$\mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)] + \lambda\,\mathbb{E}[\operatorname{Cov}(T,U\mid A^*)]$.
636	For the confounding term: since $T=\alpha_U U+\eta$ with $(U,\eta)$ jointly Gaussian, the regression residual $\xi=U-\frac{\alpha_U}{\operatorname{Var}(T)}T$ satisfies $\xi\perp T$.
637	Because $A$ is a function of $T$ (plus independent softmax noise) and $A^*$ is a function of $A$ (plus independent misclassification noise), $\xi\perp(T,A,A^*)$.
638	Therefore
639	\[
640	  \operatorname{Cov}(T,U\mid A^*{=}j)
641	  = \frac{\alpha_U}{\operatorname{Var}(T)}\,\operatorname{Var}(T\mid A^*{=}j)
642	  \quad\forall\;j,
643	\]
644	and $\lambda\,\mathbb{E}[\operatorname{Cov}(T,U\mid A^*)]=\frac{\lambda\alpha_U}{\operatorname{Var}(T)}\,D(C)$, yielding the constant first term after division by $D(C)$.
645	\end{proof}
646	
647	This decomposition reveals that \emph{misclassification does not affect the confounding component}.
648	The confusion matrix $C$ modulates only the mediation-type leakage $B_{\mathrm{med}}(C)$, which has the same structure as in~§\ref{app:mediation}.
649	
650	\paragraph{Endpoint analysis.}
651	At $C=I$: $B_{\mathrm{med}}(I)=0$ (controlling $A$ blocks the $T\to A\to Y$ path), and $\operatorname{plim}\hat\tau(I)=\lambda\alpha_U/\operatorname{Var}(T)$ (pure confounding residual).
652	
653	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$: $B_{\mathrm{med}}=\operatorname{Cov}(T,f(A))/\operatorname{Var}(T)$, and $\operatorname{plim}\hat\tau_{\mathrm{nc}}=[\operatorname{Cov}(T,f(A))+\lambda\alpha_U]/\operatorname{Var}(T)$, the naive regression coefficient with no controls.
654	
655	\paragraph{Numerical Verification (Front-door sign preservation).}
656	\label{find:fd_sign}
657	Since $B_{\mathrm{med}}(C)$ has the same structure as the mediation bias (§\ref{app:mediation})---interpolating between $0$ at $C{=}I$ and $\operatorname{Cov}(T,f(A))/\operatorname{Var}(T)$ at $C$ uniform---sign preservation holds whenever the two endpoints have the same sign:
658	\[
659	  \operatorname{sign}\!\bigl(\lambda\alpha_U\bigr)
660	  = \operatorname{sign}\!\bigl(\lambda\alpha_U + \operatorname{Cov}(T,f(A))\bigr).
661	\]
662	This result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$.
663	
664	\paragraph{Verification for paper parameters ($K{=}3$).}
665	With $\alpha_U{=}1.0$, $\lambda{=}1.0$, $\boldsymbol{\beta}{=}(0,1.0,{-}0.5)$, $\boldsymbol{\gamma}{=}(0,0.5,{-}0.3)$, $\boldsymbol{\delta}{=}(0,1.0,{-}0.8)$:
666	\begin{align*}
667	  \lambda\alpha_U/\operatorname{Var}(T) &= 1.0\times 1.0\,/\,2.0 = 0.500,\\
668	  \operatorname{Cov}(T,f(A))/\operatorname{Var}(T) &= 0.594\,/\,2.0 = 0.297.
669	\end{align*}
670	Both components are positive, so $\operatorname{plim}\hat\tau(C)\in[0.500,\,0.797]>0$ for all $C$.
671	
672	\subsection{Exposure Topology: Sign Reversal Counterexample}
673	\label{app:exposure}
674	
675	\begin{proposition}[Exposure sign reversal]
676	\label{prop:exp_counter}
677	For $K{=}3$ with $A$ as the treatment variable, there exist a marginal distribution $\mathbf{p}$, treatment effects $\boldsymbol{\beta}$, and a column-stochastic $C$ with $C_{kk}>0.5$ for all $k$, such that $\operatorname{sign}(\operatorname{plim}\hat\beta_1)\neq\operatorname{sign}(\beta_1)$.
678	\end{proposition}
679	
680	\begin{proof}[Construction]
681	Consider the exposure DGP $Y = \beta_1 D_1 + \beta_2 D_2 + \varepsilon_Y$ with:
682	\begin{itemize}
683	  \item Uniform prior: $\mathbf{p}=(1/3,\,1/3,\,1/3)$.
684	  \item True effects: $\beta_1=1$,\; $\beta_2=-10$.
685	\end{itemize}
686	Choose the confusion matrix
687	\[
688	  C = \begin{pmatrix}
689	    0.60 & 0.10 & 0.10\\
690	    0.10 & 0.60 & 0.39\\
691	    0.30 & 0.30 & 0.51
692	  \end{pmatrix},\qquad
693	  C_{kk}\in\{0.60,\,0.60,\,0.51\},\;\text{all}>0.5.
694	\]
695	Column sums are $1$ (verifiable by inspection).
696	
697	The OLS estimator regresses $Y$ on $(1,D_1^*,D_2^*)$.
698	The plim of $\hat\beta_j$ equals $\mathbb{E}[Y\mid A^*{=}j]-\mathbb{E}[Y\mid A^*{=}0]$, where
699	\[
700	  \mathbb{E}[Y\mid A^*{=}j] = \sum_{k=0}^{2} P(A{=}k\mid A^*{=}j)\,\beta_k
701	  = \sum_{k=1}^{2}\frac{C_{jk}\,p_k}{q_j}\,\beta_k.
702	\]
703	
704	\emph{Marginal distribution of $A^*$:}
705	\begin{align*}
706	  q_0 &= \tfrac{1}{3}(0.60+0.10+0.10)=0.267,\\
707	  q_1 &= \tfrac{1}{3}(0.10+0.60+0.39)=0.363,\\
708	  q_2 &= \tfrac{1}{3}(0.30+0.30+0.51)=0.370.
709	\end{align*}
710	
711	\emph{Conditional means:}
712	\begin{align*}
713	  \mathbb{E}[Y\mid A^*{=}0]
714	  &= \frac{0.10\times\tfrac{1}{3}\times 1 + 0.10\times\tfrac{1}{3}\times({-}10)}{0.267}
715	  = \frac{0.0333-0.3333}{0.267} = -1.125,\\[4pt]
716	  \mathbb{E}[Y\mid A^*{=}1]
717	  &= \frac{0.60\times\tfrac{1}{3}\times 1 + 0.39\times\tfrac{1}{3}\times({-}10)}{0.363}
718	  = \frac{0.200-1.300}{0.363} = -3.028,\\[4pt]
719	  \mathbb{E}[Y\mid A^*{=}2]
720	  &= \frac{0.30\times\tfrac{1}{3}\times 1 + 0.51\times\tfrac{1}{3}\times({-}10)}{0.370}
721	  = \frac{0.100-1.700}{0.370} = -4.324.
722	\end{align*}
723	
724	\emph{Estimated coefficient:}
725	\[
726	  \operatorname{plim}\hat\beta_1 = \mathbb{E}[Y\mid A^*{=}1]-\mathbb{E}[Y\mid A^*{=}0]
727	  = -3.028-(-1.125) = \mathbf{-1.903}.
728	\]
729	The true $\beta_1=+1>0$ but $\operatorname{plim}\hat\beta_1=-1.903<0$: \textbf{sign reversal}.
730	
731	\emph{Mechanism.}
732	The large off-diagonal entry $C_{12}=0.39$ (probability of classifying true category~2 as $A^*{=}1$) routes substantial probability mass from category~2 ($\beta_2=-10$) into the $A^*{=}1$ bin.
733	Despite $C_{11}=0.60>0.5$, the contamination from the strongly negative $\beta_2$ overwhelms the positive $\beta_1$, reversing the sign of the estimated effect for category~1.
734	This failure mode is structurally impossible at $K{=}2$: a $2{\times}2$ column-stochastic matrix with $C_{kk}>0.5$ has the form $C=\bigl(\begin{smallmatrix}a&1{-}b\\1{-}a&b\end{smallmatrix}\bigr)$ with $a,b>0.5$, and the single coefficient $\hat\beta_1$ is a positive-weighted average of $\beta_1$, preserving sign.
735	For $K{\geq}3$, the additional degrees of freedom in $C$ permit cross-contamination between categories with opposite-sign effects.
736	\end{proof}
737	
738	\subsection{Summary of Conditions}
739	\label{app:conditions}
740	
741	\begin{table}[h]
742	\centering
743	\small
744	\begin{tabular}{lccc}
745	\toprule
746	\textbf{Topology} & \textbf{Sufficient condition} & \textbf{Status} & \textbf{Paper DGP} \\
747	\midrule
748	Confounding & $\operatorname{sign}(\tau)=\operatorname{sign}(\tau{+}B_{\mathrm{OV}})$ & Proved & $\checkmark$ ($2.0$ vs $2.3$)\\
749	Collider & $|\tau|>\bar{B}_{\mathrm{col}}$ (Prop.~\ref{prop:col_gen}) & Proved & $\checkmark$ ($1.0$ vs $0.15$)\\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4b792006-d419-4e4d-b42d-90e795c7077c",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "003bf7a7-60a5-4bf8-b56c-499c13e3106f",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\label{prop:col_prop}\nIf $h(A)=\\lambda\\,g(A)$ for some constant $\\lambda$, then $|B(C)|\\leq|B(I)|$ for all column-stochastic $C$, and $B(C)$ has the same sign as $B(I)$.\nConsequently, $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau)=\\operatorname{sign}(\\tau)$ whenever $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau+B_{\\mathrm{Berkson}})$.\n\\end{proposition}\n\n\\begin{proof}\nWhen $h=\\lambda g$, the numerator becomes $-\\lambda\\,\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])$ and the denominator is $\\operatorname{Var}(T)-\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])$.\nLet $V^*=\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*])\\in[0,V_g]$ where $V_g=\\operatorname{Var}(g(A))$.\nThen\n\\[\n  |B(C)| = |\\lambda|\\,\\frac{V^*}{\\operatorname{Var}(T)-V^*}.\n\\]\nThe function $x\\mapsto x/(a-x)$ is increasing on $[0,a)$.\nWith $a=\\operatorname{Var}(T)>V_g\\geq V^*$:\n$|B(C)|\\leq|\\lambda|\\,V_g/(\\operatorname{Var}(T)-V_g)=|B(I)|$.\nAt $V^*{=}0$ (uniform $C$): $B{=}0$.  At $V^*{=}V_g$ ($C{=}I$): $B{=}B(I)$.\n\\end{proof}\n\n\\begin{proposition}[Collider sign preservation --- general case]\n\\label{prop:col_gen}\nDefine\n\\begin{equation}\n  \\bar{B}_{\\mathrm{col}} = \\frac{\\sqrt{\\operatorname{Var}(g(A))\\,\\operatorname{Var}(h(A))}}{\\mathbb{E}[\\operatorname{Var}(T\\mid A)]}.\n  \\label{eq:bbar_col}\n\\end{equation}\nIf $|\\tau|>\\bar{B}_{\\mathrm{col}}$, then $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau(C))=\\operatorname{sign}(\\tau)$ for all column-stochastic $C$.\n\\end{proposition}\n\n\\begin{proof}\n\\emph{Step~1: Bound the numerator.}\nBy Cauchy--Schwarz:\n$|\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[h\\mid A^*])|\\leq\\sqrt{\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])\\,\\operatorname{Var}(\\mathbb{E}[h\\mid A^*])}$.\nSince conditional expectation reduces variance: $\\operatorname{Var}(\\mathbb{E}[g\\mid A^*])\\leq\\operatorname{Var}(g(A))$ and likewise for $h$.\n\n\\emph{Step~2: Bound the denominator.}\n$\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]=\\operatorname{Var}(T)-\\operatorname{Var}(\\mathbb{E}[T\\mid A^*])\\geq\\operatorname{Var}(T)-\\operatorname{Var}(g(A))=\\mathbb{E}[\\operatorname{Var}(T\\mid A)]$.\n\n\\emph{Step~3: Conclude.}\n$|B(C)|\\leq\\sqrt{\\operatorname{Var}(g)\\,\\operatorname{Var}(h)}\\,/\\,\\mathbb{E}[\\operatorname{Var}(T\\mid A)]=\\bar{B}_{\\mathrm{col}}$.\nWhen $|\\tau|>\\bar{B}_{\\mathrm{col}}$, the bias cannot overwhelm $\\tau$. In practice, $\\operatorname{Var}(g(A))$ and $\\operatorname{Var}(h(A))$ can be estimated from observable data by bootstrapping regression coefficients from $A^*$-stratified subsamples, yielding conservative upper bounds on $\\bar{B}_{\\mathrm{col}}$.\n\\end{proof}\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\tau{=}1.0$, $\\boldsymbol{\\delta}_T{=}(0,\\,0.5,\\,{-}0.3)$, $\\boldsymbol{\\delta}_Y{=}(0,\\,0.8,\\,0.6)$, from $5{\\times}10^6$-sample Monte Carlo:\n\\begin{align*}\n  \\operatorname{Var}(g(A)) &= 0.187,\\quad\n  \\operatorname{Var}(h(A)) = 0.076,\\quad\n  \\mathbb{E}[\\operatorname{Var}(T\\mid A)] = 0.813,\\\\\n  \\bar{B}_{\\mathrm{col}} &= \\sqrt{0.187\\times 0.076}\\;/\\;0.813 = 0.147.\n\\end{align*}\nSince $|\\tau|{=}1.0\\gg\\bar{B}_{\\mathrm{col}}{=}0.147$, Proposition~\\ref{prop:col_gen} guarantees sign preservation.\nAdditionally, $B_{\\mathrm{Berkson}}{=}{-}0.114$, giving $\\tau+B_{\\mathrm{Berkson}}{=}0.886{>}0$.\nVerified across $100{,}000$ random column-stochastic $C$: $\\tau_{\\mathrm{sign\\,flip}}{=}0\\%$, and $|B(C)|\\leq|B_{\\mathrm{Berkson}}|$ in all cases.\n\n\\subsection{Front-door Topology ($A$ = Mediator under Confounding)}\n\\label{app:frontdoor}\n\n\\paragraph{Data-generating process.}\n$T\\to A\\to Y$, $U\\to T$, $U\\to Y$.\nAn unobserved confounder $U$ affects both treatment and outcome:\n\\begin{align*}\n  U &\\sim \\mathcal{N}(0,1),\\quad\n  T = \\alpha_U\\,U + \\eta,\\quad \\eta\\sim\\mathcal{N}(0,1),\\;\\eta\\perp U,\\\\\n  A\\mid T &\\sim \\operatorname{Categorical}\\bigl(\\operatorname{softmax}(\\boldsymbol{\\gamma}+\\boldsymbol{\\delta}\\,T)\\bigr),\\\\\n  Y &= f(A) + \\lambda\\,U + \\varepsilon_Y,\\quad \\varepsilon_Y\\perp(T,A,U).\n\\end{align*}\nThere is no direct $T{\\to}Y$ edge; the causal effect of $T$ on $Y$ operates entirely through $A$.\nThe researcher controls for $A^*$ in $Y\\sim 1+T+D_1^*+\\cdots+D_{K-1}^*$.\n\n\\paragraph{Bias decomposition.}\nSince the direct effect is zero, the FWL coefficient on $T$ captures only bias:\n\\[\n  \\operatorname{plim}\\hat\\tau(C) = \\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,Y\\mid A^*)]}{\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]}.\n\\]\nSubstituting $Y=f(A)+\\lambda U+\\varepsilon_Y$ and using $\\varepsilon_Y\\perp(T,A,A^*)$:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C)\n  = \\underbrace{\\frac{\\lambda\\,\\alpha_U}{\\operatorname{Var}(T)}}_{\\text{confounding (constant)}}\n  \\;+\\; \\underbrace{\\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)]}{D(C)}}_{\\displaystyle B_{\\mathrm{med}}(C)},\n  \\label{eq:fd_decomp}\n\\end{equation}\nwhere $D(C)=\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]$.\n\n\\begin{proof}[Derivation of~\\eqref{eq:fd_decomp}]\nExpand the numerator as\n$\\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)] + \\lambda\\,\\mathbb{E}[\\operatorname{Cov}(T,U\\mid A^*)]$.\nFor the confounding term: since $T=\\alpha_U U+\\eta$ with $(U,\\eta)$ jointly Gaussian, the regression residual $\\xi=U-\\frac{\\alpha_U}{\\operatorname{Var}(T)}T$ satisfies $\\xi\\perp T$.\nBecause $A$ is a function of $T$ (plus independent softmax noise) and $A^*$ is a function of $A$ (plus independent misclassification noise), $\\xi\\perp(T,A,A^*)$.\nTherefore\n\\[\n  \\operatorname{Cov}(T,U\\mid A^*{=}j)\n  = \\frac{\\alpha_U}{\\operatorname{Var}(T)}\\,\\operatorname{Var}(T\\mid A^*{=}j)\n  \\quad\\forall\\;j,\n\\]\nand $\\lambda\\,\\mathbb{E}[\\operatorname{Cov}(T,U\\mid A^*)]=\\frac{\\lambda\\alpha_U}{\\operatorname{Var}(T)}\\,D(C)$, yielding the constant first term after division by $D(C)$.\n\\end{proof}\n\nThis decomposition reveals that \\emph{misclassification does not affect the confounding component}.\nThe confusion matrix $C$ modulates only the mediation-type leakage $B_{\\mathrm{med}}(C)$, which has the same structure as in~§\\ref{app:mediation}.\n\n\\paragraph{Endpoint analysis.}\nAt $C=I$: $B_{\\mathrm{med}}(I)=0$ (controlling $A$ blocks the $T\\to A\\to Y$ path), and $\\operatorname{plim}\\hat\\tau(I)=\\lambda\\alpha_U/\\operatorname{Var}(T)$ (pure confounding residual).\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$: $B_{\\mathrm{med}}=\\operatorname{Cov}(T,f(A))/\\operatorname{Var}(T)$, and $\\operatorname{plim}\\hat\\tau_{\\mathrm{nc}}=[\\operatorname{Cov}(T,f(A))+\\lambda\\alpha_U]/\\operatorname{Var}(T)$, the naive regression coefficient with no controls.\n\n\\paragraph{Numerical Verification (Front-door sign preservation).}\n\\label{find:fd_sign}\nSince $B_{\\mathrm{med}}(C)$ has the same structure as the mediation bias (§\\ref{app:mediation})---interpolating between $0$ at $C{=}I$ and $\\operatorname{Cov}(T,f(A))/\\operatorname{Var}(T)$ at $C$ uniform---sign preservation holds whenever the two endpoints have the same sign:\n\\[\n  \\operatorname{sign}\\!\\bigl(\\lambda\\alpha_U\\bigr)\n  = \\operatorname{sign}\\!\\bigl(\\lambda\\alpha_U + \\operatorname{Cov}(T,f(A))\\bigr).\n\\]\nThis result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$.\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\alpha_U{=}1.0$, $\\lambda{=}1.0$, $\\boldsymbol{\\beta}{=}(0,1.0,{-}0.5)$, $\\boldsymbol{\\gamma}{=}(0,0.5,{-}0.3)$, $\\boldsymbol{\\delta}{=}(0,1.0,{-}0.8)$:\n\\begin{align*}\n  \\lambda\\alpha_U/\\operatorname{Var}(T) &= 1.0\\times 1.0\\,/\\,2.0 = 0.500,\\\\\n  \\operatorname{Cov}(T,f(A))/\\operatorname{Var}(T) &= 0.594\\,/\\,2.0 = 0.297.\n\\end{align*}\nBoth components are positive, so $\\operatorname{plim}\\hat\\tau(C)\\in[0.500,\\,0.797]>0$ for all $C$.\n\n\\subsection{Exposure Topology: Sign Reversal Counterexample}\n\\label{app:exposure}\n\n\\begin{proposition}[Exposure sign reversal]\n\\label{prop:exp_counter}\nFor $K{=}3$ with $A$ as the treatment variable, there exist a marginal distribution $\\mathbf{p}$, treatment effects $\\boldsymbol{\\beta}$, and a column-stochastic $C$ with $C_{kk}>0.5$ for all $k$, such that $\\operatorname{sign}(\\operatorname{plim}\\hat\\beta_1)\\neq\\operatorname{sign}(\\beta_1)$.\n\\end{proposition}\n\n\\begin{proof}[Construction]\nConsider the exposure DGP $Y = \\beta_1 D_1 + \\beta_2 D_2 + \\varepsilon_Y$ with:\n\\begin{itemize}\n  \\item Uniform prior: $\\mathbf{p}=(1/3,\\,1/3,\\,1/3)$.\n  \\item True effects: $\\beta_1=1$,\\; $\\beta_2=-10$.\n\\end{itemize}\nChoose the confusion matrix\n\\[\n  C = \\begin{pmatrix}\n    0.60 & 0.10 & 0.10\\\\\n    0.10 & 0.60 & 0.39\\\\\n    0.30 & 0.30 & 0.51\n  \\end{pmatrix},\\qquad\n  C_{kk}\\in\\{0.60,\\,0.60,\\,0.51\\},\\;\\text{all}>0.5.\n\\]\nColumn sums are $1$ (verifiable by inspection).\n\nThe OLS estimator regresses $Y$ on $(1,D_1^*,D_2^*)$.\nThe plim of $\\hat\\beta_j$ equals $\\mathbb{E}[Y\\mid A^*{=}j]-\\mathbb{E}[Y\\mid A^*{=}0]$, where\n\\[\n  \\mathbb{E}[Y\\mid A^*{=}j] = \\sum_{k=0}^{2} P(A{=}k\\mid A^*{=}j)\\,\\beta_k\n  = \\sum_{k=1}^{2}\\frac{C_{jk}\\,p_k}{q_j}\\,\\beta_k.\n\\]\n\n\\emph{Marginal distribution of $A^*$:}\n\\begin{align*}\n  q_0 &= \\tfrac{1}{3}(0.60+0.10+0.10)=0.267,\\\\\n  q_1 &= \\tfrac{1}{3}(0.10+0.60+0.39)=0.363,\\\\\n  q_2 &= \\tfrac{1}{3}(0.30+0.30+0.51)=0.370.\n\\end{align*}\n\n\\emph{Conditional means:}\n\\begin{align*}\n  \\mathbb{E}[Y\\mid A^*{=}0]\n  &= \\frac{0.10\\times\\tfrac{1}{3}\\times 1 + 0.10\\times\\tfrac{1}{3}\\times({-}10)}{0.267}\n  = \\frac{0.0333-0.3333}{0.267} = -1.125,\\\\[4pt]\n  \\mathbb{E}[Y\\mid A^*{=}1]\n  &= \\frac{0.60\\times\\tfrac{1}{3}\\times 1 + 0.39\\times\\tfrac{1}{3}\\times({-}10)}{0.363}\n  = \\frac{0.200-1.300}{0.363} = -3.028,\\\\[4pt]\n  \\mathbb{E}[Y\\mid A^*{=}2]\n  &= \\frac{0.30\\times\\tfrac{1}{3}\\times 1 + 0.51\\times\\tfrac{1}{3}\\times({-}10)}{0.370}\n  = \\frac{0.100-1.700}{0.370} = -4.324.\n\\end{align*}\n\n\\emph{Estimated coefficient:}\n\\[\n  \\operatorname{plim}\\hat\\beta_1 = \\mathbb{E}[Y\\mid A^*{=}1]-\\mathbb{E}[Y\\mid A^*{=}0]\n  = -3.028-(-1.125) = \\mathbf{-1.903}.\n\\]\nThe true $\\beta_1=+1>0$ but $\\operatorname{plim}\\hat\\beta_1=-1.903<0$: \\textbf{sign reversal}.\n\n\\emph{Mechanism.}\nThe large off-diagonal entry $C_{12}=0.39$ (probability of classifying true category~2 as $A^*{=}1$) routes substantial probability mass from category~2 ($\\beta_2=-10$) into the $A^*{=}1$ bin.\nDespite $C_{11}=0.60>0.5$, the contamination from the strongly negative $\\beta_2$ overwhelms the positive $\\beta_1$, reversing the sign of the estimated effect for category~1.\nThis failure mode is structurally impossible at $K{=}2$: a $2{\\times}2$ column-stochastic matrix with $C_{kk}>0.5$ has the form $C=\\bigl(\\begin{smallmatrix}a&1{-}b\\\\1{-}a&b\\end{smallmatrix}\\bigr)$ with $a,b>0.5$, and the single coefficient $\\hat\\beta_1$ is a positive-weighted average of $\\beta_1$, preserving sign.\nFor $K{\\geq}3$, the additional degrees of freedom in $C$ permit cross-contamination between categories with opposite-sign effects.\n\\end{proof}\n\n\\subsection{Summary of Conditions}\n\\label{app:conditions}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Sufficient condition} & \\textbf{Status} & \\textbf{Paper DGP} \\\\\n\\midrule\nConfounding & $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau{+}B_{\\mathrm{OV}})$ & Proved & $\\checkmark$ ($2.0$ vs $2.3$)\\\\\nCollider & $|\\tau|>\\bar{B}_{\\mathrm{col}}$ (Prop.~\\ref{prop:col_gen}) & Proved & $\\checkmark$ ($1.0$ vs $0.15$)\\\\",
      "numLines": 200,
      "startLine": 550,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "4b792006-d419-4e4d-b42d-90e795c7077c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 68 · 2026-05-24T06:37:15.825Z_

<details><summary>↩ Tool result · `toolu_017BBzdVY2LHfiTDVGefvvNF`</summary>

```text
200	  &\leq \mathbb{E}\bigl[\sqrt{\operatorname{Var}(g\mid A^*)\,\operatorname{Var}(f\mid A^*)}\bigr]\\
201	  &\leq \sqrt{\mathbb{E}[\operatorname{Var}(g\mid A^*)]\;\mathbb{E}[\operatorname{Var}(f\mid A^*)]}\\
202	  &\leq \sqrt{\operatorname{Var}(g(A))\;\operatorname{Var}(f(A))},
203	\end{align*}
204	where the last step uses $\mathbb{E}[\operatorname{Var}(X\mid Y)]\leq\operatorname{Var}(X)$ (law of total variance).
205	
206	\emph{Step 2: Conclude.}
207	The bias satisfies
208	\[
209	  |B(C)| = \frac{|R(C)|}{D(C)} \leq \frac{\sqrt{\operatorname{Var}(g)\,\operatorname{Var}(f)}}{\sigma_T^2} = \bar{B}.
210	\]
211	When $|\tau|>\bar{B}$, the bias cannot cancel $\tau$, so $\operatorname{sign}(\operatorname{plim}\hat\tau)=\operatorname{sign}(\tau)$ for all $C$.
212	\end{proof}
213	
214	\paragraph{Relationship to the omitted-variable condition.}
215	A weaker (necessary) condition for sign preservation is $\operatorname{sign}(\tau)=\operatorname{sign}(\tau_{\mathrm{OV}})$ where $\tau_{\mathrm{OV}}=\tau+\operatorname{Cov}(g,f)/\operatorname{Var}(T)$.
216	If this fails, then $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ (uniform noise) already flips the sign.
217	The rigorous sufficient condition $|\tau|>\bar{B}$ implies the weaker condition, since $|B_{\mathrm{OV}}|=|\operatorname{Cov}(g,f)|/\operatorname{Var}(T)\leq\bar{B}$ by Cauchy--Schwarz and $\operatorname{Var}(T)\geq\sigma_T^2$.
218	
219	\paragraph{Verification for paper parameters ($K{=}3$).}
220	With $\tau{=}2.0$, $\boldsymbol{\alpha}{=}(1.5,{-}1.0)$, $\boldsymbol{\beta}^{(A)}{=}(1.0,{-}0.5)$, $\sigma_T{=}1.0$, $\mathbf{p}{=}(0.40,0.35,0.25)$:
221	\begin{align*}
222	  \operatorname{Var}(g) &= \sum_k p_k\alpha_k^2 - \bigl(\textstyle\sum_k p_k\alpha_k\bigr)^2 = 0.962,\\
223	  \operatorname{Var}(f) &= \sum_k p_k(\beta_k^{(A)})^2 - \bigl(\textstyle\sum_k p_k\beta_k^{(A)}\bigr)^2 = 0.362,\\
224	  \bar{B} &= \sqrt{0.962\times 0.362}\;/\;1.0^2 = 0.590.
225	\end{align*}
226	Since $|\tau|{=}2.0 > \bar{B}{=}0.590$, sign preservation is guaranteed for \emph{all} column-stochastic $C$ by Proposition~\ref{prop:conf_gen}.
227	Additionally, $B_{\mathrm{OV}}=\operatorname{Cov}(g,f)/\operatorname{Var}(T)=0.588/1.962={+}0.300$, giving $\tau_{\mathrm{OV}}{=}2.300>0$, confirming that both the necessary and sufficient conditions are satisfied.
228	
229	\paragraph{Extension to $K > 3$.}
230	For $K{>}3$, treatment effect coefficients are drawn from a fixed pool with alternating signs and decreasing magnitudes: $\boldsymbol{\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3, \ldots)$, truncated to $K$ entries. The category distribution uses $p_k \propto 1/(k{+}1)$, normalized to sum to 1. Other topology-specific parameters (confounding strengths, mediator effects, etc.) follow analogous alternating-sign pools. For $K{=}10$, $\boldsymbol{\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3)$.
231	
232	\subsection{Proof of Theorem~\ref{thm:monotone} (Confounding Monotonicity)}
233	\label{app:monotonicity_proof}
234	
235	Under the interpolation $C(\delta)=(1{-}\delta)I+\delta C_0$, we prove $|B(C(\delta))|$ is non-decreasing in $\delta$ for proportional effects ($f=\lambda g$) and provide numerical verification for the general case.
236	The proof proceeds by direct algebraic analysis of $V_B(\delta)=\operatorname{Var}(\mathbb{E}[g(A)\mid A^*_\delta])$ as a rational function of $\delta$, establishing convexity and bounding the derivative at both endpoints.
237	
238	\paragraph{Proportional case ($f=\lambda g$).}
239	From Proposition~\ref{prop:conf_prop}, $B(C)=\lambda V_W/(V_W+\sigma_T^2)$ where $V_W=\operatorname{Var}(g)-V_B$ and $V_B(\delta)=\operatorname{Var}(\mathbb{E}[g(A)\mid A^*_\delta])$.
240	
241	\emph{Step 1: Convexity of $V_B(\delta)$.}
242	Define $N_j(\delta)=\sum_k g_k\,C(\delta)_{jk}\,p_k$ and $q_j(\delta)=\sum_k C(\delta)_{jk}\,p_k$.
243	Both are affine in $\delta$, with $q_j(\delta)>0$.
244	Then $V_B(\delta)=\sum_j N_j(\delta)^2/q_j(\delta) - \bar{g}^2$.
245	Each term $N_j^2/q_j$ is the composition of the perspective function $(x,t)\mapsto x^2/t$ (convex for $t>0$) with the affine map $\delta\mapsto(N_j(\delta),\,q_j(\delta))$, hence convex in $\delta$.
246	A sum of convex functions is convex, so $V_B(\delta)$ is convex on $[0,\delta_{\max}]$.
247	
248	\emph{Step 2: Derivative formula.}
249	Let $\mu_j(\delta)=N_j(\delta)/q_j(\delta)=\mathbb{E}[g(A)\mid A^*{=}j]$.
250	Then
251	\begin{equation}
252	\frac{dV_B}{d\delta}
253	= -\sum_{j,k}\bigl[(C_0)_{jk}-\mathbf{1}_{j=k}\bigr]\,p_k\,(g_k-\mu_j(\delta))^2.
254	\label{eq:dVB}
255	\end{equation}
256	\emph{Derivation.}
257	$\frac{d}{d\delta}\frac{N_j^2}{q_j}=2\mu_j\dot{N}_j-\mu_j^2\dot{q}_j$
258	where $\dot{N}_j=m_j^0-g_jp_j$ and $\dot{q}_j=q_j^0-p_j$ (with $m_j^0=\sum_k g_k(C_0)_{jk}p_k$, $q_j^0=\sum_k(C_0)_{jk}p_k$).
259	Substituting and using column-stochasticity ($\sum_j(C_0)_{jk}=\sum_j\mathbf{1}_{j=k}=1$) to cancel the $g_k^2$ terms yields~\eqref{eq:dVB}.
260	
261	\emph{Step 3: $V_B'(0)\leq 0$ (universal, no conditions on $C_0$).}
262	At $\delta{=}0$: $\mu_j(0)=g_j$ (since $C(0)=I$), so $(g_k-\mu_j(0))^2=(g_k-g_j)^2$.
263	The diagonal terms ($j{=}k$) vanish.
264	Hence
265	\[
266	V_B'(0)=-\sum_{j\neq k}(C_0)_{jk}\,p_k\,(g_j-g_k)^2\;\leq\; 0,
267	\]
268	since every term is non-negative.
269	
270	\emph{Step 4: $V_B'(1)\leq 0$ for $K{=}2$.}
271	For $K{=}2$ with $C_0=\bigl[\begin{smallmatrix}a&1{-}b\\1{-}a&b\end{smallmatrix}\bigr]$ and $a,b\geq\tfrac{1}{2}$,
272	set $g_0{=}0$, $g_1{=}1$ without loss of generality
273	(the general case scales by $(\Delta g)^2$).
274	At $\delta{=}1$: $q_0{=}ap_0{+}(1{-}b)p_1$, $q_1{=}(1{-}a)p_0{+}bp_1$,
275	$\mu_0{=}(1{-}b)p_1/q_0$, $\mu_1{=}bp_1/q_1$.
276	Expanding~\eqref{eq:dVB} at $\delta{=}1$ and factoring:
277	\begin{align*}
278	  V_B'(1) &= (1{-}a)\,p_0(\mu_0^2{-}\mu_1^2)+(1{-}b)\,p_1\bigl[(1{-}\mu_1)^2{-}(1{-}\mu_0)^2\bigr] \\
279	  &= (\mu_0{-}\mu_1)\,\bigl[(1{-}a)\,p_0(\mu_0{+}\mu_1)+(1{-}b)\,p_1(2{-}\mu_0{-}\mu_1)\bigr].
280	\end{align*}
281	The bracket is non-negative (since $0\leq\mu_j\leq 1$ and all coefficients are non-negative).
282	Direct calculation gives $\mu_0{-}\mu_1=p_0\,p_1(1{-}a{-}b)/(q_0\,q_1)$
283	(expand $(1{-}b)\,q_1-b\,q_0=p_0(1{-}a{-}b)$).
284	Under $a,b\geq\tfrac{1}{2}$: $a{+}b\geq 1$, so $\mu_0{-}\mu_1\leq 0$ and $V_B'(1)\leq 0$.
285	
286	\emph{Step 5: Monotonicity from convexity.}
287	Since $V_B$ is convex (Step~1), its derivative $V_B'$ is non-decreasing.
288	When $V_B'(1)\leq 0$, we have $V_B'(\delta)\leq V_B'(1)\leq 0$ for all $\delta\in[0,1]$, so $V_B$ is non-increasing.
289	
290	\emph{Step 6: $|B(\delta)|$ is non-decreasing.}
291	$V_W(\delta)=\operatorname{Var}(g)-V_B(\delta)$ is non-decreasing (Step~5).
292	The function $h(x)=|\lambda|\,x/(x+\sigma_T^2)$ is strictly increasing for $x\geq 0$.
293	Hence $|B(\delta)|=h(V_W(\delta))$ is non-decreasing. \qed
294	
295	\paragraph{Condition on $C_0$.}
296	The proof requires $V_B'(1)\leq 0$, which is guaranteed for $K{=}2$ when $(C_0)_{jj}\geq\tfrac{1}{2}$ (Step~4).
297	For $K\geq 3$, $V_B'(1)\leq 0$ holds for all $g$ and $p$ if and only if a certain matrix $M-W$ (depending on $C_0$ and $p$) is negative semi-definite; simple diagonal thresholds are sufficient in practice but not universal.
298	Numerical verification across 20{,}000 random $(C_0,p,g)$ triples per $K\in\{3,5,7\}$ with $(C_0)_{jj}\geq 1/K$ finds worst-case $|B|$ step deviations $< 0.013$ (Table~\ref{tab:conjecture_verify}), confirming $\varepsilon$-approximate monotonicity.
299	A $K{=}2$ counterexample ($C_0$ the permutation matrix, $(C_0)_{jj}{=}0$) shows the diagonal condition is necessary: $V_B(\delta)=(\delta{-}\tfrac{1}{2})^2$ increases on $(\tfrac{1}{2},1]$.
300	
301	\paragraph{General case (non-proportional effects).}
302	$|B(C(\delta))|\leq\bar{B}(\delta)$ where $\bar{B}(\delta)=\sqrt{\mathbb{E}[\operatorname{Var}(g\mid A^*_\delta)]\,\mathbb{E}[\operatorname{Var}(f\mid A^*_\delta)]}\,/\,D(\delta)$ (Proposition~\ref{prop:conf_gen}).
303	By the same convexity argument, each $\mathbb{E}[\operatorname{Var}(\cdot\mid A^*_\delta)]$ is non-decreasing in $\delta$, and $D(\delta)=\mathbb{E}[\operatorname{Var}(T\mid A^*_\delta)]$ is non-decreasing.
304	Extended verification (20{,}000 random $C_0$ matrices, $K \in \{3,5,7\}$) reveals worst-case step deviations of 0.011 (confounding), confirming approximate tightness; a strict monotonicity proof for the general case remains open.
305	
306	\begin{remark}[Conditional exact monotonicity]
307	\label{rem:conditional_monotonicity}
308	Exact monotonicity ($V_B'(\delta) \leq 0$ for all $\delta$) holds under the \emph{component-wise diagonal dominance} condition:
309	\begin{equation}
310	  \alpha_j \geq \frac{q_j}{p_j + q_j} \quad \text{for all } j,
311	  \label{eq:dd_condition}
312	\end{equation}
313	where $\alpha_j = (C_0)_{jj}$ and $q_j = \sum_k (C_0)_{jk} p_k$. This condition requires that each class's classification accuracy exceeds a threshold determined by its spillover ratio $q_j/p_j$. The proof uses Cauchy--Schwarz on the endpoint derivative decomposition $V_B'(1) = \sum_j (p_j + q_j)\,e_j^2 - \sum_{j \neq k} (C_0)_{jk}\,p_k\,(g_j - g_k)^2$, where $e_j = g_j - \mu_j$ (full proof in supplementary material).
314	
315	For doubly stochastic $C_0$ with uniform $p$, condition~\eqref{eq:dd_condition} reduces to $\alpha_j \geq 1/2$, which for $K{=}2$ recovers the exact condition in Theorem~\ref{thm:monotone}. Numerical testing ($10^5$ random column-stochastic matrices with $\alpha_j \geq 0.5$) shows the condition holds in $99.3\%$ of cases; the $0.7\%$ violations arise predominantly under class imbalance with maximum step deviation $< 0.001$. When the condition fails, a quantitative bound $V_B'(1) \leq (1{-}c)^2 R_g^2$ (where $c = \min_j \alpha_j$ and $R_g = \max g_k - \min g_k$) ensures violations vanish as classifier accuracy improves.
316	\end{remark}
317	
318	\subsection{Mediation Topology ($A$ = Mediator)}
319	\label{app:mediation}
320	
321	\paragraph{Data-generating process.}
322	$T\to A\to Y$, $T\to Y$.
323	\begin{align*}
324	  T &\sim \operatorname{Bernoulli}(0.5),\\
325	  A\mid T &\sim \operatorname{Categorical}\bigl(\operatorname{softmax}(\boldsymbol{\gamma}+\boldsymbol{\delta}\,T)\bigr),\\
326	  Y &= \tau_{\mathrm{dir}}\,T + f(A) + \varepsilon_Y.
327	\end{align*}
328	
329	\paragraph{Bias decomposition.}
330	By Lemma~\ref{lem:bias_decomp}, the direct-effect estimator satisfies:
331	\begin{equation}
332	  \operatorname{plim}\hat\tau_{\mathrm{dir}}(C) = \tau_{\mathrm{dir}} + \frac{\mathbb{E}[\operatorname{Cov}(T,\,f(A)\mid A^*)]}{D(C)}.
333	  \label{eq:med_bias}
334	\end{equation}
335	
336	The key structural difference from confounding: $T$ \emph{causes} $A$, so the residual covariance $\operatorname{Cov}(T,f(A)\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.
337	
338	\paragraph{Endpoint analysis.}
339	
340	At $C=I$ ($A^*{=}A$): conditioning on $A$ blocks the mediated path $T\to A\to Y$, so $\operatorname{Cov}(T,f(A)\mid A)=0$ and $\operatorname{plim}\hat\tau=\tau_{\mathrm{dir}}$.
341	
342	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ ($A^*\perp A$): no information about $A$ is used, and
343	\begin{align*}
344	  \mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)] &= \operatorname{Cov}(T,f(A)),\\
345	  D(C) &= \operatorname{Var}(T) = 0.25.
346	\end{align*}
347	The indirect effect is $\tau_{\mathrm{ind}}=\mathbb{E}[f(A)\mid T{=}1]-\mathbb{E}[f(A)\mid T{=}0]$, and
348	\[
349	  \operatorname{Cov}(T,f(A)) = 0.25\,\tau_{\mathrm{ind}}.
350	\]
351	Hence at $C$ uniform: $\operatorname{plim}\hat\tau = \tau_{\mathrm{dir}}+\tau_{\mathrm{ind}} = \tau_{\mathrm{total}}$.
352	
353	\paragraph{Numerical Verification (Mediation sign preservation).}
354	\label{find:med_sign}
355	$\operatorname{sign}(\operatorname{plim}\hat\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{dir}})$ whenever $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$, where $\tau_{\mathrm{total}}=\tau_{\mathrm{dir}}+\tau_{\mathrm{ind}}$.
356	This result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$; a closed-form proof for general $K$ remains open.
357	
358	\begin{proof}
359	Let $R(C)=\mathbb{E}[\operatorname{Cov}(T,f(A)\mid A^*)]$ and $D(C)=\mathbb{E}[\operatorname{Var}(T\mid A^*)]>0$.
360	
361	\emph{Endpoints.}
362	At $C{=}I$: $f(A)$ is constant given $A{=}A^*$, so $R(I)=0$ and $B(I)=0$.
363	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$: $R=\operatorname{Cov}(T,f(A))=0.25\,\tau_{\mathrm{ind}}$ and $D=\operatorname{Var}(T)=0.25$, giving $B=\tau_{\mathrm{ind}}$.
364	
365	\emph{Within-group structure for binary $T$.}
366	Since $T\in\{0,1\}$, the within-$A^*$-group bias admits a revealing decomposition.
367	Let $p_j=P(T{=}1\mid A^*{=}j)$.
368	Then $\operatorname{Var}(T\mid A^*{=}j)=p_j(1{-}p_j)$ and
369	\[
370	  \operatorname{Cov}(T,f(A)\mid A^*{=}j)
371	  = p_j(1{-}p_j)\bigl[\mathbb{E}[f(A)\mid T{=}1,A^*{=}j]-\mathbb{E}[f(A)\mid T{=}0,A^*{=}j]\bigr].
372	\]
373	Define $\delta_j=\mathbb{E}[f(A)\mid T{=}1,A^*{=}j]-\mathbb{E}[f(A)\mid T{=}0,A^*{=}j]$ as the \emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.
374	Then
375	\[
376	  B(C)=\frac{R(C)}{D(C)}
377	  =\frac{\sum_j q_j\,p_j(1{-}p_j)\,\delta_j}{\sum_j q_j\,p_j(1{-}p_j)}
378	  =\sum_j w_j\,\delta_j,
379	\]
380	a weighted average of the conditional indirect effects, with weights $w_j=q_j p_j(1{-}p_j)/\sum_\ell q_\ell p_\ell(1{-}p_\ell)\geq 0$ summing to 1.
381	
382	At $C{=}I$: each $A^*{=}j$ group has $A{=}j$ a.s., so $\delta_j=f(j)-f(j)=0$ and $B=0$.
383	At $C$ uniform: $\delta_j=\tau_{\mathrm{ind}}$ for all $j$ and $B=\tau_{\mathrm{ind}}$.
384	
385	\emph{Sign preservation.}
386	When $\operatorname{Cov}(g(A),f(A))>0$ (the indirect effect reinforces the direct effect, i.e., $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{ind}}$ have the same sign), the bias $B(C)\geq 0$ cannot oppose $\tau_{\mathrm{dir}}$, so sign is preserved trivially.
387	
388	When $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{ind}}$ have opposite signs but $|\tau_{\mathrm{ind}}|<|\tau_{\mathrm{dir}}|$ (i.e., $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$), sign reversal requires some $|\delta_j|>|\tau_{\mathrm{dir}}|$ with the opposing sign.
389	Since each $\delta_j$ is a difference of weighted averages of $f$ values (with weights $P(A{=}k\mid T{=}t,A^*{=}j)$), and $B(C)$ is a convex combination of $\delta_j$, the bound $|B(C)|\leq\max_j|\delta_j|$ holds.
390	We verify numerically that $\max_j|\delta_j|\leq|\tau_{\mathrm{ind}}|$ for all 100{,}000 random $C$ matrices in our experiments, confirming sign preservation.
391	\end{proof}
392	
393	\paragraph{Verification for paper parameters ($K{=}3$).}
394	With $\tau_{\mathrm{dir}}{=}0.5$, $\boldsymbol{\gamma}{=}(0,0,0)$, $\boldsymbol{\delta}{=}(0,0.8,{-}0.6)$, $\boldsymbol{\beta}{=}(0,1.0,{-}0.5)$:
395	
396	$\tau_{\mathrm{ind}}=\mathbb{E}[f(A)\mid T{=}1]-\mathbb{E}[f(A)\mid T{=}0]=0.351$ (computed from the softmax class probabilities).
397	$\tau_{\mathrm{total}}=0.5+0.351=0.851>0$.
398	Since $\tau_{\mathrm{dir}}{>}0$ and $\tau_{\mathrm{total}}{>}0$, sign preservation holds for all $C$.
399	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cecb6751-e2a6-49fa-8165-30566fe642e6",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "0a869c6b-d4df-4247-8725-08b67ef39bce",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "  &\\leq \\mathbb{E}\\bigl[\\sqrt{\\operatorname{Var}(g\\mid A^*)\\,\\operatorname{Var}(f\\mid A^*)}\\bigr]\\\\\n  &\\leq \\sqrt{\\mathbb{E}[\\operatorname{Var}(g\\mid A^*)]\\;\\mathbb{E}[\\operatorname{Var}(f\\mid A^*)]}\\\\\n  &\\leq \\sqrt{\\operatorname{Var}(g(A))\\;\\operatorname{Var}(f(A))},\n\\end{align*}\nwhere the last step uses $\\mathbb{E}[\\operatorname{Var}(X\\mid Y)]\\leq\\operatorname{Var}(X)$ (law of total variance).\n\n\\emph{Step 2: Conclude.}\nThe bias satisfies\n\\[\n  |B(C)| = \\frac{|R(C)|}{D(C)} \\leq \\frac{\\sqrt{\\operatorname{Var}(g)\\,\\operatorname{Var}(f)}}{\\sigma_T^2} = \\bar{B}.\n\\]\nWhen $|\\tau|>\\bar{B}$, the bias cannot cancel $\\tau$, so $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau)=\\operatorname{sign}(\\tau)$ for all $C$.\n\\end{proof}\n\n\\paragraph{Relationship to the omitted-variable condition.}\nA weaker (necessary) condition for sign preservation is $\\operatorname{sign}(\\tau)=\\operatorname{sign}(\\tau_{\\mathrm{OV}})$ where $\\tau_{\\mathrm{OV}}=\\tau+\\operatorname{Cov}(g,f)/\\operatorname{Var}(T)$.\nIf this fails, then $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ (uniform noise) already flips the sign.\nThe rigorous sufficient condition $|\\tau|>\\bar{B}$ implies the weaker condition, since $|B_{\\mathrm{OV}}|=|\\operatorname{Cov}(g,f)|/\\operatorname{Var}(T)\\leq\\bar{B}$ by Cauchy--Schwarz and $\\operatorname{Var}(T)\\geq\\sigma_T^2$.\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\tau{=}2.0$, $\\boldsymbol{\\alpha}{=}(1.5,{-}1.0)$, $\\boldsymbol{\\beta}^{(A)}{=}(1.0,{-}0.5)$, $\\sigma_T{=}1.0$, $\\mathbf{p}{=}(0.40,0.35,0.25)$:\n\\begin{align*}\n  \\operatorname{Var}(g) &= \\sum_k p_k\\alpha_k^2 - \\bigl(\\textstyle\\sum_k p_k\\alpha_k\\bigr)^2 = 0.962,\\\\\n  \\operatorname{Var}(f) &= \\sum_k p_k(\\beta_k^{(A)})^2 - \\bigl(\\textstyle\\sum_k p_k\\beta_k^{(A)}\\bigr)^2 = 0.362,\\\\\n  \\bar{B} &= \\sqrt{0.962\\times 0.362}\\;/\\;1.0^2 = 0.590.\n\\end{align*}\nSince $|\\tau|{=}2.0 > \\bar{B}{=}0.590$, sign preservation is guaranteed for \\emph{all} column-stochastic $C$ by Proposition~\\ref{prop:conf_gen}.\nAdditionally, $B_{\\mathrm{OV}}=\\operatorname{Cov}(g,f)/\\operatorname{Var}(T)=0.588/1.962={+}0.300$, giving $\\tau_{\\mathrm{OV}}{=}2.300>0$, confirming that both the necessary and sufficient conditions are satisfied.\n\n\\paragraph{Extension to $K > 3$.}\nFor $K{>}3$, treatment effect coefficients are drawn from a fixed pool with alternating signs and decreasing magnitudes: $\\boldsymbol{\\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3, \\ldots)$, truncated to $K$ entries. The category distribution uses $p_k \\propto 1/(k{+}1)$, normalized to sum to 1. Other topology-specific parameters (confounding strengths, mediator effects, etc.) follow analogous alternating-sign pools. For $K{=}10$, $\\boldsymbol{\\beta} = (0, 1.0, {-}0.5, 0.7, {-}0.3, 0.5, {-}0.2, 0.4, {-}0.15, 0.3)$.\n\n\\subsection{Proof of Theorem~\\ref{thm:monotone} (Confounding Monotonicity)}\n\\label{app:monotonicity_proof}\n\nUnder the interpolation $C(\\delta)=(1{-}\\delta)I+\\delta C_0$, we prove $|B(C(\\delta))|$ is non-decreasing in $\\delta$ for proportional effects ($f=\\lambda g$) and provide numerical verification for the general case.\nThe proof proceeds by direct algebraic analysis of $V_B(\\delta)=\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*_\\delta])$ as a rational function of $\\delta$, establishing convexity and bounding the derivative at both endpoints.\n\n\\paragraph{Proportional case ($f=\\lambda g$).}\nFrom Proposition~\\ref{prop:conf_prop}, $B(C)=\\lambda V_W/(V_W+\\sigma_T^2)$ where $V_W=\\operatorname{Var}(g)-V_B$ and $V_B(\\delta)=\\operatorname{Var}(\\mathbb{E}[g(A)\\mid A^*_\\delta])$.\n\n\\emph{Step 1: Convexity of $V_B(\\delta)$.}\nDefine $N_j(\\delta)=\\sum_k g_k\\,C(\\delta)_{jk}\\,p_k$ and $q_j(\\delta)=\\sum_k C(\\delta)_{jk}\\,p_k$.\nBoth are affine in $\\delta$, with $q_j(\\delta)>0$.\nThen $V_B(\\delta)=\\sum_j N_j(\\delta)^2/q_j(\\delta) - \\bar{g}^2$.\nEach term $N_j^2/q_j$ is the composition of the perspective function $(x,t)\\mapsto x^2/t$ (convex for $t>0$) with the affine map $\\delta\\mapsto(N_j(\\delta),\\,q_j(\\delta))$, hence convex in $\\delta$.\nA sum of convex functions is convex, so $V_B(\\delta)$ is convex on $[0,\\delta_{\\max}]$.\n\n\\emph{Step 2: Derivative formula.}\nLet $\\mu_j(\\delta)=N_j(\\delta)/q_j(\\delta)=\\mathbb{E}[g(A)\\mid A^*{=}j]$.\nThen\n\\begin{equation}\n\\frac{dV_B}{d\\delta}\n= -\\sum_{j,k}\\bigl[(C_0)_{jk}-\\mathbf{1}_{j=k}\\bigr]\\,p_k\\,(g_k-\\mu_j(\\delta))^2.\n\\label{eq:dVB}\n\\end{equation}\n\\emph{Derivation.}\n$\\frac{d}{d\\delta}\\frac{N_j^2}{q_j}=2\\mu_j\\dot{N}_j-\\mu_j^2\\dot{q}_j$\nwhere $\\dot{N}_j=m_j^0-g_jp_j$ and $\\dot{q}_j=q_j^0-p_j$ (with $m_j^0=\\sum_k g_k(C_0)_{jk}p_k$, $q_j^0=\\sum_k(C_0)_{jk}p_k$).\nSubstituting and using column-stochasticity ($\\sum_j(C_0)_{jk}=\\sum_j\\mathbf{1}_{j=k}=1$) to cancel the $g_k^2$ terms yields~\\eqref{eq:dVB}.\n\n\\emph{Step 3: $V_B'(0)\\leq 0$ (universal, no conditions on $C_0$).}\nAt $\\delta{=}0$: $\\mu_j(0)=g_j$ (since $C(0)=I$), so $(g_k-\\mu_j(0))^2=(g_k-g_j)^2$.\nThe diagonal terms ($j{=}k$) vanish.\nHence\n\\[\nV_B'(0)=-\\sum_{j\\neq k}(C_0)_{jk}\\,p_k\\,(g_j-g_k)^2\\;\\leq\\; 0,\n\\]\nsince every term is non-negative.\n\n\\emph{Step 4: $V_B'(1)\\leq 0$ for $K{=}2$.}\nFor $K{=}2$ with $C_0=\\bigl[\\begin{smallmatrix}a&1{-}b\\\\1{-}a&b\\end{smallmatrix}\\bigr]$ and $a,b\\geq\\tfrac{1}{2}$,\nset $g_0{=}0$, $g_1{=}1$ without loss of generality\n(the general case scales by $(\\Delta g)^2$).\nAt $\\delta{=}1$: $q_0{=}ap_0{+}(1{-}b)p_1$, $q_1{=}(1{-}a)p_0{+}bp_1$,\n$\\mu_0{=}(1{-}b)p_1/q_0$, $\\mu_1{=}bp_1/q_1$.\nExpanding~\\eqref{eq:dVB} at $\\delta{=}1$ and factoring:\n\\begin{align*}\n  V_B'(1) &= (1{-}a)\\,p_0(\\mu_0^2{-}\\mu_1^2)+(1{-}b)\\,p_1\\bigl[(1{-}\\mu_1)^2{-}(1{-}\\mu_0)^2\\bigr] \\\\\n  &= (\\mu_0{-}\\mu_1)\\,\\bigl[(1{-}a)\\,p_0(\\mu_0{+}\\mu_1)+(1{-}b)\\,p_1(2{-}\\mu_0{-}\\mu_1)\\bigr].\n\\end{align*}\nThe bracket is non-negative (since $0\\leq\\mu_j\\leq 1$ and all coefficients are non-negative).\nDirect calculation gives $\\mu_0{-}\\mu_1=p_0\\,p_1(1{-}a{-}b)/(q_0\\,q_1)$\n(expand $(1{-}b)\\,q_1-b\\,q_0=p_0(1{-}a{-}b)$).\nUnder $a,b\\geq\\tfrac{1}{2}$: $a{+}b\\geq 1$, so $\\mu_0{-}\\mu_1\\leq 0$ and $V_B'(1)\\leq 0$.\n\n\\emph{Step 5: Monotonicity from convexity.}\nSince $V_B$ is convex (Step~1), its derivative $V_B'$ is non-decreasing.\nWhen $V_B'(1)\\leq 0$, we have $V_B'(\\delta)\\leq V_B'(1)\\leq 0$ for all $\\delta\\in[0,1]$, so $V_B$ is non-increasing.\n\n\\emph{Step 6: $|B(\\delta)|$ is non-decreasing.}\n$V_W(\\delta)=\\operatorname{Var}(g)-V_B(\\delta)$ is non-decreasing (Step~5).\nThe function $h(x)=|\\lambda|\\,x/(x+\\sigma_T^2)$ is strictly increasing for $x\\geq 0$.\nHence $|B(\\delta)|=h(V_W(\\delta))$ is non-decreasing. \\qed\n\n\\paragraph{Condition on $C_0$.}\nThe proof requires $V_B'(1)\\leq 0$, which is guaranteed for $K{=}2$ when $(C_0)_{jj}\\geq\\tfrac{1}{2}$ (Step~4).\nFor $K\\geq 3$, $V_B'(1)\\leq 0$ holds for all $g$ and $p$ if and only if a certain matrix $M-W$ (depending on $C_0$ and $p$) is negative semi-definite; simple diagonal thresholds are sufficient in practice but not universal.\nNumerical verification across 20{,}000 random $(C_0,p,g)$ triples per $K\\in\\{3,5,7\\}$ with $(C_0)_{jj}\\geq 1/K$ finds worst-case $|B|$ step deviations $< 0.013$ (Table~\\ref{tab:conjecture_verify}), confirming $\\varepsilon$-approximate monotonicity.\nA $K{=}2$ counterexample ($C_0$ the permutation matrix, $(C_0)_{jj}{=}0$) shows the diagonal condition is necessary: $V_B(\\delta)=(\\delta{-}\\tfrac{1}{2})^2$ increases on $(\\tfrac{1}{2},1]$.\n\n\\paragraph{General case (non-proportional effects).}\n$|B(C(\\delta))|\\leq\\bar{B}(\\delta)$ where $\\bar{B}(\\delta)=\\sqrt{\\mathbb{E}[\\operatorname{Var}(g\\mid A^*_\\delta)]\\,\\mathbb{E}[\\operatorname{Var}(f\\mid A^*_\\delta)]}\\,/\\,D(\\delta)$ (Proposition~\\ref{prop:conf_gen}).\nBy the same convexity argument, each $\\mathbb{E}[\\operatorname{Var}(\\cdot\\mid A^*_\\delta)]$ is non-decreasing in $\\delta$, and $D(\\delta)=\\mathbb{E}[\\operatorname{Var}(T\\mid A^*_\\delta)]$ is non-decreasing.\nExtended verification (20{,}000 random $C_0$ matrices, $K \\in \\{3,5,7\\}$) reveals worst-case step deviations of 0.011 (confounding), confirming approximate tightness; a strict monotonicity proof for the general case remains open.\n\n\\begin{remark}[Conditional exact monotonicity]\n\\label{rem:conditional_monotonicity}\nExact monotonicity ($V_B'(\\delta) \\leq 0$ for all $\\delta$) holds under the \\emph{component-wise diagonal dominance} condition:\n\\begin{equation}\n  \\alpha_j \\geq \\frac{q_j}{p_j + q_j} \\quad \\text{for all } j,\n  \\label{eq:dd_condition}\n\\end{equation}\nwhere $\\alpha_j = (C_0)_{jj}$ and $q_j = \\sum_k (C_0)_{jk} p_k$. This condition requires that each class's classification accuracy exceeds a threshold determined by its spillover ratio $q_j/p_j$. The proof uses Cauchy--Schwarz on the endpoint derivative decomposition $V_B'(1) = \\sum_j (p_j + q_j)\\,e_j^2 - \\sum_{j \\neq k} (C_0)_{jk}\\,p_k\\,(g_j - g_k)^2$, where $e_j = g_j - \\mu_j$ (full proof in supplementary material).\n\nFor doubly stochastic $C_0$ with uniform $p$, condition~\\eqref{eq:dd_condition} reduces to $\\alpha_j \\geq 1/2$, which for $K{=}2$ recovers the exact condition in Theorem~\\ref{thm:monotone}. Numerical testing ($10^5$ random column-stochastic matrices with $\\alpha_j \\geq 0.5$) shows the condition holds in $99.3\\%$ of cases; the $0.7\\%$ violations arise predominantly under class imbalance with maximum step deviation $< 0.001$. When the condition fails, a quantitative bound $V_B'(1) \\leq (1{-}c)^2 R_g^2$ (where $c = \\min_j \\alpha_j$ and $R_g = \\max g_k - \\min g_k$) ensures violations vanish as classifier accuracy improves.\n\\end{remark}\n\n\\subsection{Mediation Topology ($A$ = Mediator)}\n\\label{app:mediation}\n\n\\paragraph{Data-generating process.}\n$T\\to A\\to Y$, $T\\to Y$.\n\\begin{align*}\n  T &\\sim \\operatorname{Bernoulli}(0.5),\\\\\n  A\\mid T &\\sim \\operatorname{Categorical}\\bigl(\\operatorname{softmax}(\\boldsymbol{\\gamma}+\\boldsymbol{\\delta}\\,T)\\bigr),\\\\\n  Y &= \\tau_{\\mathrm{dir}}\\,T + f(A) + \\varepsilon_Y.\n\\end{align*}\n\n\\paragraph{Bias decomposition.}\nBy Lemma~\\ref{lem:bias_decomp}, the direct-effect estimator satisfies:\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C) = \\tau_{\\mathrm{dir}} + \\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)]}{D(C)}.\n  \\label{eq:med_bias}\n\\end{equation}\n\nThe key structural difference from confounding: $T$ \\emph{causes} $A$, so the residual covariance $\\operatorname{Cov}(T,f(A)\\mid A^*)$ captures the indirect effect of $T$ on $Y$ through $A$ that is not absorbed by conditioning on $A^*$.\n\n\\paragraph{Endpoint analysis.}\n\nAt $C=I$ ($A^*{=}A$): conditioning on $A$ blocks the mediated path $T\\to A\\to Y$, so $\\operatorname{Cov}(T,f(A)\\mid A)=0$ and $\\operatorname{plim}\\hat\\tau=\\tau_{\\mathrm{dir}}$.\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ ($A^*\\perp A$): no information about $A$ is used, and\n\\begin{align*}\n  \\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)] &= \\operatorname{Cov}(T,f(A)),\\\\\n  D(C) &= \\operatorname{Var}(T) = 0.25.\n\\end{align*}\nThe indirect effect is $\\tau_{\\mathrm{ind}}=\\mathbb{E}[f(A)\\mid T{=}1]-\\mathbb{E}[f(A)\\mid T{=}0]$, and\n\\[\n  \\operatorname{Cov}(T,f(A)) = 0.25\\,\\tau_{\\mathrm{ind}}.\n\\]\nHence at $C$ uniform: $\\operatorname{plim}\\hat\\tau = \\tau_{\\mathrm{dir}}+\\tau_{\\mathrm{ind}} = \\tau_{\\mathrm{total}}$.\n\n\\paragraph{Numerical Verification (Mediation sign preservation).}\n\\label{find:med_sign}\n$\\operatorname{sign}(\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{dir}})$ whenever $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$, where $\\tau_{\\mathrm{total}}=\\tau_{\\mathrm{dir}}+\\tau_{\\mathrm{ind}}$.\nThis result is verified numerically for $100{,}000$ independently sampled column-stochastic matrices $C$; a closed-form proof for general $K$ remains open.\n\n\\begin{proof}\nLet $R(C)=\\mathbb{E}[\\operatorname{Cov}(T,f(A)\\mid A^*)]$ and $D(C)=\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]>0$.\n\n\\emph{Endpoints.}\nAt $C{=}I$: $f(A)$ is constant given $A{=}A^*$, so $R(I)=0$ and $B(I)=0$.\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$: $R=\\operatorname{Cov}(T,f(A))=0.25\\,\\tau_{\\mathrm{ind}}$ and $D=\\operatorname{Var}(T)=0.25$, giving $B=\\tau_{\\mathrm{ind}}$.\n\n\\emph{Within-group structure for binary $T$.}\nSince $T\\in\\{0,1\\}$, the within-$A^*$-group bias admits a revealing decomposition.\nLet $p_j=P(T{=}1\\mid A^*{=}j)$.\nThen $\\operatorname{Var}(T\\mid A^*{=}j)=p_j(1{-}p_j)$ and\n\\[\n  \\operatorname{Cov}(T,f(A)\\mid A^*{=}j)\n  = p_j(1{-}p_j)\\bigl[\\mathbb{E}[f(A)\\mid T{=}1,A^*{=}j]-\\mathbb{E}[f(A)\\mid T{=}0,A^*{=}j]\\bigr].\n\\]\nDefine $\\delta_j=\\mathbb{E}[f(A)\\mid T{=}1,A^*{=}j]-\\mathbb{E}[f(A)\\mid T{=}0,A^*{=}j]$ as the \\emph{conditional indirect effect} in the $A^*{=}j$ subpopulation.\nThen\n\\[\n  B(C)=\\frac{R(C)}{D(C)}\n  =\\frac{\\sum_j q_j\\,p_j(1{-}p_j)\\,\\delta_j}{\\sum_j q_j\\,p_j(1{-}p_j)}\n  =\\sum_j w_j\\,\\delta_j,\n\\]\na weighted average of the conditional indirect effects, with weights $w_j=q_j p_j(1{-}p_j)/\\sum_\\ell q_\\ell p_\\ell(1{-}p_\\ell)\\geq 0$ summing to 1.\n\nAt $C{=}I$: each $A^*{=}j$ group has $A{=}j$ a.s., so $\\delta_j=f(j)-f(j)=0$ and $B=0$.\nAt $C$ uniform: $\\delta_j=\\tau_{\\mathrm{ind}}$ for all $j$ and $B=\\tau_{\\mathrm{ind}}$.\n\n\\emph{Sign preservation.}\nWhen $\\operatorname{Cov}(g(A),f(A))>0$ (the indirect effect reinforces the direct effect, i.e., $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{ind}}$ have the same sign), the bias $B(C)\\geq 0$ cannot oppose $\\tau_{\\mathrm{dir}}$, so sign is preserved trivially.\n\nWhen $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{ind}}$ have opposite signs but $|\\tau_{\\mathrm{ind}}|<|\\tau_{\\mathrm{dir}}|$ (i.e., $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$), sign reversal requires some $|\\delta_j|>|\\tau_{\\mathrm{dir}}|$ with the opposing sign.\nSince each $\\delta_j$ is a difference of weighted averages of $f$ values (with weights $P(A{=}k\\mid T{=}t,A^*{=}j)$), and $B(C)$ is a convex combination of $\\delta_j$, the bound $|B(C)|\\leq\\max_j|\\delta_j|$ holds.\nWe verify numerically that $\\max_j|\\delta_j|\\leq|\\tau_{\\mathrm{ind}}|$ for all 100{,}000 random $C$ matrices in our experiments, confirming sign preservation.\n\\end{proof}\n\n\\paragraph{Verification for paper parameters ($K{=}3$).}\nWith $\\tau_{\\mathrm{dir}}{=}0.5$, $\\boldsymbol{\\gamma}{=}(0,0,0)$, $\\boldsymbol{\\delta}{=}(0,0.8,{-}0.6)$, $\\boldsymbol{\\beta}{=}(0,1.0,{-}0.5)$:\n\n$\\tau_{\\mathrm{ind}}=\\mathbb{E}[f(A)\\mid T{=}1]-\\mathbb{E}[f(A)\\mid T{=}0]=0.351$ (computed from the softmax class probabilities).\n$\\tau_{\\mathrm{total}}=0.5+0.351=0.851>0$.\nSince $\\tau_{\\mathrm{dir}}{>}0$ and $\\tau_{\\mathrm{total}}{>}0$, sign preservation holds for all $C$.\n",
      "numLines": 200,
      "startLine": 200,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "cecb6751-e2a6-49fa-8165-30566fe642e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 69 · 2026-05-24T06:37:16.608Z_

<details open><summary>🔧 Tool call — Read · `toolu_01T9VCsh3EtWxzKL7Rgs8GeV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 400,
  "limit": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0a869c6b-d4df-4247-8725-08b67ef39bce",
  "isSidechain": false,
  "requestId": "req_011CbLvwvQgvQBtz9tpEKbR1",
  "type": "assistant",
  "uuid": "745735b2-7584-4a75-aa6c-1020ffe626e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AKVMaUPAMGdh4mPtfBLzZa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4664,
      "cache_read_input_tokens": 60058,
      "output_tokens": 2599,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4664,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2599,
          "cache_read_input_tokens": 60058,
          "cache_creation_input_tokens": 4664,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4664
          },
          "type": "message"
        }
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

_source line 70 · 2026-05-24T06:37:16.614Z_

<details><summary>↩ Tool result · `toolu_01T9VCsh3EtWxzKL7Rgs8GeV`</summary>

```text
400	\paragraph{Mediation monotonicity (proportional effects).}
401	\label{par:med_monotone}
402	
403	Under the interpolation $C(\delta)=(1{-}\delta)I+\delta C_0$, we prove $|B(C(\delta))|$ is non-decreasing in $\delta$ when the mediator's effect on $Y$ is proportional to its informativeness about $T$: $f(A)=\lambda\,g(A)$ for some scalar $\lambda$, where $g(k)=\mathbb{E}[T\mid A{=}k]$.
404	
405	\emph{Step 1: Decompose $T$ via the mediator.}
406	Define $g(A)=\mathbb{E}[T\mid A]$ and $\varepsilon_T = T - g(A)$.
407	By construction, $\mathbb{E}[\varepsilon_T\mid A]=0$.
408	By non-differential misclassification ($T\perp A^*\mid A$):
409	$\mathbb{E}[\varepsilon_T\mid A{=}k, A^*{=}j] = 0$,
410	so $\mathbb{E}[\varepsilon_T\mid A^*{=}j]=0$ and $\operatorname{Cov}(\varepsilon_T,\,g(A)\mid A^*{=}j)=0$ for every $j$.
411	
412	\emph{Step 2: Reduce the numerator.}
413	Since $f=\lambda g$:
414	\begin{align*}
415	  R(C) &= \lambda\,\mathbb{E}[\operatorname{Var}(g(A)\mid A^*)] = \lambda\,V_W.
416	\end{align*}
417	
418	\emph{Step 3: Constant additive term in denominator.}
419	\begin{align*}
420	  D(C) &= \mathbb{E}[\operatorname{Var}(T\mid A^*)]
421	       = V_W + \sigma_\varepsilon^2,
422	\end{align*}
423	where $\sigma_\varepsilon^2\equiv\mathbb{E}[\operatorname{Var}(\varepsilon_T\mid A^*)]$.
424	This is \emph{constant} (independent of $C$):
425	$\mathbb{E}[\operatorname{Var}(\varepsilon_T\mid A^*)]
426	  = \sum_k p_k\,\operatorname{Var}(T\mid A{=}k)
427	  = \mathbb{E}[\operatorname{Var}(T\mid A)]$,
428	where the equality uses column-stochasticity: $\sum_j q_j\,P(A{=}k\mid A^*{=}j)=p_k$.
429	
430	\emph{Step 4: Closed form and monotonicity.}
431	$B(C) = \lambda\,V_W/(V_W+\sigma_\varepsilon^2)$,
432	structurally identical to confounding (Proposition~\ref{prop:conf_prop}) with $\sigma_\varepsilon^2$ playing the role of $\sigma_T^2$.
433	Since $V_B(\delta)$ is convex with $V_B'(0)\leq 0$ (same argument as \S\ref{app:monotonicity_proof}, Steps~1--3), $V_W(\delta)=V{-}V_B(\delta)$ is non-decreasing under the same conditions on $C_0$.
434	Since $h(x)=|\lambda|x/(x+\sigma_\varepsilon^2)$ is increasing, $|B(C(\delta))|$ is non-decreasing.
435	
436	\paragraph{Boundedness of the leakage coefficient.}
437	
438	The mediation bias~\eqref{eq:mediation} writes the residual indirect effect as $(1-\lambda(C))\,\tau_{\mathrm{ind}}$, which (for $\tau_{\mathrm{ind}}\neq 0$) \emph{implicitly} defines
439	\begin{equation}
440	\label{eq:lambda_def}
441	  \lambda(C) \;:=\; 1-\frac{B(C)}{\tau_{\mathrm{ind}}},\qquad
442	  B(C)\;\equiv\;\operatorname{plim}\hat{\tau}_{\mathrm{dir}}(A^*)-\tau_{\mathrm{dir}},\quad
443	  \tau_{\mathrm{ind}}\;=\;\frac{\operatorname{Cov}(T,f(A))}{\operatorname{Var}(T)}.
444	\end{equation}
445	Substituting back into~\eqref{eq:mediation} gives the convex-combination form
446	$\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)=\lambda(C)\,\tau_{\mathrm{dir}}+(1-\lambda(C))\,\tau_{\mathrm{total}}$, so $\lambda(C)$ is the weight placing the biased plim between $\tau_{\mathrm{dir}}$ (perfect classification) and $\tau_{\mathrm{total}}$ (no information).
447	
448	\begin{proposition}[Mediation leakage boundedness]
449	\label{prop:lambda_bound}
450	Let $\lambda(C)$ be defined by~\eqref{eq:lambda_def} with $\tau_{\mathrm{ind}}\neq 0$, and let $C$ be column-stochastic.
451	\begin{enumerate}
452	\item[(a)] $\lambda(C)\leq 1$ iff $\operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$ (the bias points in the direction of the indirect effect; no overcorrection).
453	\item[(b)] $\lambda(C)\geq 0$ iff additionally $|B(C)|\leq|\tau_{\mathrm{ind}}|$ (the bias does not exceed the indirect effect in magnitude).
454	\end{enumerate}
455	Equivalently, $\lambda(C)\in[0,1]$ iff $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)\in[\min(\tau_{\mathrm{dir}},\tau_{\mathrm{total}}),\,\max(\tau_{\mathrm{dir}},\tau_{\mathrm{total}})]$.
456	
457	Under \emph{proportional effects} ($f(A)=\lambda_0\,g(A)$ with $g(k)=\mathbb{E}[T\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\lambda(C)\in[0,1]$ unconditionally.
458	For \emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\operatorname{Cov}(\mathbb{E}[g\mid A^*],\mathbb{E}[f\mid A^*])$ may differ in sign or magnitude from $\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.
459	The endpoints $\lambda(I)=1$ and $\lambda(C)\to 0$ in the rank-one (uninformative) limit hold in all regimes.
460	
461	\emph{Sign preservation.} When $\lambda(C)\in[0,1]$, the convex-combination form gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)\in[\min(\tau_{\mathrm{dir}},\tau_{\mathrm{total}}),\,\max(\tau_{\mathrm{dir}},\tau_{\mathrm{total}})]$. If additionally $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$, both endpoints share the same sign, so $\operatorname{sign}(\operatorname{plim}\hat\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{dir}})$ for every~$C$. Under proportional effects, $\lambda(C)\in[0,1]$ is automatic (above), so sign preservation of $\hat\tau_{\mathrm{dir}}$ reduces to the single condition $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
462	\end{proposition}
463	
464	\begin{proof}
465	\emph{(a),(b).} With $\tau_{\mathrm{ind}}\neq 0$, $\lambda(C)\leq 1\iff B(C)/\tau_{\mathrm{ind}}\geq 0\iff \operatorname{sign}(B(C))=\operatorname{sign}(\tau_{\mathrm{ind}})$. Given (a), $\lambda(C)\geq 0\iff B(C)/\tau_{\mathrm{ind}}\leq 1\iff|B(C)|\leq|\tau_{\mathrm{ind}}|$.
466	
467	\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\lambda_0\,V_W(C)/(V_W(C)+\sigma_\varepsilon^2)$; the rank-one limit $V_W{\to}V$ yields $\tau_{\mathrm{ind}}=\lambda_0\,V/(V+\sigma_\varepsilon^2)$. Both quantities carry $\operatorname{sign}(\lambda_0)$, establishing~(a). The ratio
468	\[
469	  \frac{B(C)}{\tau_{\mathrm{ind}}}\;=\;\frac{V_W(C)\,(V+\sigma_\varepsilon^2)}{V\,(V_W(C)+\sigma_\varepsilon^2)}
470	\]
471	is monotone increasing in $V_W(C)\in[0,V]$ with range $[0,1]$ (its derivative in $V_W$ is $\sigma_\varepsilon^2(V+\sigma_\varepsilon^2)/[V(V_W+\sigma_\varepsilon^2)^2]>0$), establishing~(b). Hence $\lambda(C)\in[0,1]$ unconditionally.
472	
473	\emph{General case.} Substituting $\lambda(C)$ from~\eqref{eq:lambda_def} into~\eqref{eq:mediation} yields $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)=\lambda(C)\,\tau_{\mathrm{dir}}+(1{-}\lambda(C))\,\tau_{\mathrm{total}}$, so $\lambda(C)\in[0,1]$ iff $\operatorname{plim}\hat\tau_{\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\tau_{\mathrm{dir}}$ and $\tau_{\mathrm{total}}$.
474	
475	\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\mathbb{E}[T\mid A^*]=g(A)$, and FWL gives $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\tau_{\mathrm{dir}}$, hence $B(I)=0$ and $\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\perp A$ so $\mathbb{E}[T\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\operatorname{plim}\hat\tau_{\mathrm{dir}}=\operatorname{Cov}(Y,T)/\operatorname{Var}(T)=\tau_{\mathrm{total}}$, giving $B=\tau_{\mathrm{ind}}$ and $\lambda=0$.
476	\end{proof}
477	
478	\paragraph{Relation to the between-variance ratio.}
479	A natural \emph{diagnostic} closely related to $\lambda(C)$ is the between-variance ratio
480	\begin{equation}
481	\label{eq:vb_ratio}
482	  \lambda_V(C) \;:=\; \frac{V_B(C)}{V},\qquad V_B(C)\;=\;\operatorname{Var}\!\bigl(\mathbb{E}[g(A)\mid A^*]\bigr),\quad V\;=\;\operatorname{Var}(g(A)),
483	\end{equation}
484	which satisfies $\lambda_V(C)\in[0,1]$ \emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\lambda$ and $\lambda_V$ agree at the endpoints and are related by
485	\[
486	  1-\lambda(C)\;=\;\frac{V_W(C)\,(V+\sigma_\varepsilon^2)}{V\,(V_W(C)+\sigma_\varepsilon^2)}\;=\;\bigl(1-\lambda_V(C)\bigr)\cdot\frac{V+\sigma_\varepsilon^2}{V_W(C)+\sigma_\varepsilon^2},
487	\]
488	so they coincide in the limit $\sigma_\varepsilon^2\gg V$. They generally differ for non-proportional $f$. We use $\lambda$ throughout the main text because it parameterizes~\eqref{eq:mediation} directly; $\lambda_V$ remains a useful summary of the channel quality of $A^*$ as a proxy for $A$ (independent of the structural form of $f$).
489	
490	\paragraph{Numerical verification.}
491	For each $K\in\{3,5,7\}$ we draw $N{=}10{,}000$ configurations $(\pi,g,\sigma_\varepsilon^2,C)$ with $\pi\sim\operatorname{Dirichlet}(\mathbf{1})$, $g\sim\mathcal{N}(0,I_K)$, $\sigma_\varepsilon^2\sim\operatorname{Uniform}(0.1,2)$, columns of $C\sim\operatorname{Dirichlet}(\mathbf{1})$, and evaluate $\lambda(C)$ from~\eqref{eq:lambda_def} in two regimes for $f$:
492	\begin{itemize}\itemsep0pt
493	\item \textbf{Proportional} ($f=\lambda_0\,g$, $\lambda_0\sim\mathcal{N}(0,1)\!\setminus\!\{0\}$): $\lambda(C)\in[0,1]$ in \emph{all} $30{,}000$ trials (pooled observed range $[1.2{\times}10^{-5},\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\hat\tau_{\mathrm{dir}}$ therefore reduces to $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$.
494	\item \textbf{Non-proportional} ($f\sim\mathcal{N}(0,I_K)$ drawn independently of $g$, restricted to $|\tau_{\mathrm{ind}}|\geq 0.05$ to avoid the ill-conditioned regime where $\lambda{=}1{-}B/\tau_{\mathrm{ind}}$ diverges): $\lambda(C)$ exceeds $[0,1]$ in $\sim15$--$17\%$ of trials, illustrating that (a) and (b) are not automatic outside the proportional case.
495	\end{itemize}
496	The diagnostic $\lambda_V(C)$ lies in $[0,1]$ across all $30{,}000$ trials irrespective of regime, as guaranteed by the law of total variance. The script and full results are in \texttt{artifacts/verify\_lambda\_bound.py} and \texttt{artifacts/verify\_lambda\_bound\_results.json}.
497	
498	\subsection{Proof of Theorem~\ref{thm:k3_symmetric} ($K{=}3$ Symmetric Monotonicity)}
499	\label{app:k3_symmetric_proof}
500	
501	\input{k3_symmetric_proof.tex}
502	
503	\begin{remark}[Empirical symmetry of LLM confusion matrices]
504	\label{rem:symmetry}
505	Empirical $K{=}3$ confusion matrices from LLM stance detection deviate substantially from symmetry (median relative Frobenius distance $d_{\mathrm{rel}}{=}0.33$; range 0.30--0.38 across 10 VAST configurations). Theorem~\ref{thm:k3_symmetric} thus serves as a theoretical anchor establishing that exact monotonicity is achievable at $K{=}3$ under the strongest structural assumption; practical coverage for asymmetric matrices relies on the numerical evidence of Conjecture~\ref{conj:monotone} ($\varepsilon < 0.02$ across 545{,}945 adversarial curves including non-symmetric structures).
506	\end{remark}
507	
508	\subsection{Collider Topology ($A$ = Collider)}
509	\label{app:collider}
510	
511	\paragraph{Data-generating process.}
512	$T\to A\leftarrow Y$, $T\to Y$.
513	The treatment effect is unconfounded:
514	\begin{align*}
515	  T &\sim \mathcal{N}(0,1),\quad
516	  Y = \tau\,T + \varepsilon_Y,\quad \varepsilon_Y\sim\mathcal{N}(0,1),\;\varepsilon_Y\perp T,\\
517	  A\mid T,Y &\sim \operatorname{Categorical}\bigl(\operatorname{softmax}(\boldsymbol{\delta}_T\,T + \boldsymbol{\delta}_Y\,Y)\bigr).
518	\end{align*}
519	The collider $A$ is a common \emph{effect} of $T$ and $Y$.
520	The no-control estimator (regressing $Y$ on $T$ alone) is consistent: $\operatorname{plim}\hat\tau_{\mathrm{nc}}=\tau$.
521	The researcher erroneously controls for $A^*$, inducing Berkson's bias.
522	
523	\paragraph{Bias decomposition.}
524	Unlike confounding, $\varepsilon_Y$ is not independent of $A$ (since $A$ depends on $Y=\tau T+\varepsilon_Y$), so Lemma~\ref{lem:bias_decomp} does not apply directly.
525	Instead, we derive the bias from the FWL identity~\eqref{eq:fwl}.
526	Writing $\tilde{Y}=\tau\tilde{T}+(\varepsilon_Y-\mathbb{E}[\varepsilon_Y\mid A^*])$ and noting that $\mathbb{E}[\tilde{T}\,\varepsilon_Y]=\mathbb{E}[\operatorname{Cov}(T,\varepsilon_Y\mid A^*)]$ (since $T\perp\varepsilon_Y$ unconditionally):
527	\begin{equation}
528	  \operatorname{plim}\hat\tau(C) = \tau + B(C),\quad
529	  B(C) = \frac{\mathbb{E}[\operatorname{Cov}(T,\,\varepsilon_Y\mid A^*)]}{\mathbb{E}[\operatorname{Var}(T\mid A^*)]}.
530	  \label{eq:bias_col}
531	\end{equation}
532	Under non-differential misclassification ($A^*\perp(T,\varepsilon_Y)\mid A$), define $g(k)=\mathbb{E}[T\mid A{=}k]$ and $h(k)=\mathbb{E}[\varepsilon_Y\mid A{=}k]$.
533	By the tower property, $\mathbb{E}[T\mid A^*]=\mathbb{E}[g(A)\mid A^*]$ and $\mathbb{E}[\varepsilon_Y\mid A^*]=\mathbb{E}[h(A)\mid A^*]$.
534	Since $\operatorname{Cov}(T,\varepsilon_Y)=0$, the law of total covariance gives:
535	\[
536	  B(C) = \frac{-\operatorname{Cov}\bigl(\mathbb{E}[g(A)\mid A^*],\;\mathbb{E}[h(A)\mid A^*]\bigr)}{\mathbb{E}[\operatorname{Var}(T\mid A^*)]}.
537	\]
538	
539	\paragraph{Endpoint analysis.}
540	At $C=I$ ($A^*{=}A$):
541	$B(I) = -\operatorname{Cov}(g(A),h(A))\,/\,\mathbb{E}[\operatorname{Var}(T\mid A)] = B_{\mathrm{Berkson}}$,
542	the full Berkson's bias from conditioning on the collider.
543	
544	At $C=\frac{1}{K}\mathbf{1}\mathbf{1}^\top$ ($A^*\perp A$):
545	$\mathbb{E}[g(A)\mid A^*]$ and $\mathbb{E}[h(A)\mid A^*]$ are constant, so $B=0$ and $\operatorname{plim}\hat\tau=\tau$.
546	
547	This is the structural reverse of confounding: misclassification attenuates the collider-induced bias toward zero, rather than growing bias from zero toward $B_{\mathrm{OV}}$.
548	
549	\begin{proposition}[Collider sign preservation --- proportional case]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "745735b2-7584-4a75-aa6c-1020ffe626e6",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "1f8b79bb-c3bc-453f-ad6c-2bec0d0b06b0",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\paragraph{Mediation monotonicity (proportional effects).}\n\\label{par:med_monotone}\n\nUnder the interpolation $C(\\delta)=(1{-}\\delta)I+\\delta C_0$, we prove $|B(C(\\delta))|$ is non-decreasing in $\\delta$ when the mediator's effect on $Y$ is proportional to its informativeness about $T$: $f(A)=\\lambda\\,g(A)$ for some scalar $\\lambda$, where $g(k)=\\mathbb{E}[T\\mid A{=}k]$.\n\n\\emph{Step 1: Decompose $T$ via the mediator.}\nDefine $g(A)=\\mathbb{E}[T\\mid A]$ and $\\varepsilon_T = T - g(A)$.\nBy construction, $\\mathbb{E}[\\varepsilon_T\\mid A]=0$.\nBy non-differential misclassification ($T\\perp A^*\\mid A$):\n$\\mathbb{E}[\\varepsilon_T\\mid A{=}k, A^*{=}j] = 0$,\nso $\\mathbb{E}[\\varepsilon_T\\mid A^*{=}j]=0$ and $\\operatorname{Cov}(\\varepsilon_T,\\,g(A)\\mid A^*{=}j)=0$ for every $j$.\n\n\\emph{Step 2: Reduce the numerator.}\nSince $f=\\lambda g$:\n\\begin{align*}\n  R(C) &= \\lambda\\,\\mathbb{E}[\\operatorname{Var}(g(A)\\mid A^*)] = \\lambda\\,V_W.\n\\end{align*}\n\n\\emph{Step 3: Constant additive term in denominator.}\n\\begin{align*}\n  D(C) &= \\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]\n       = V_W + \\sigma_\\varepsilon^2,\n\\end{align*}\nwhere $\\sigma_\\varepsilon^2\\equiv\\mathbb{E}[\\operatorname{Var}(\\varepsilon_T\\mid A^*)]$.\nThis is \\emph{constant} (independent of $C$):\n$\\mathbb{E}[\\operatorname{Var}(\\varepsilon_T\\mid A^*)]\n  = \\sum_k p_k\\,\\operatorname{Var}(T\\mid A{=}k)\n  = \\mathbb{E}[\\operatorname{Var}(T\\mid A)]$,\nwhere the equality uses column-stochasticity: $\\sum_j q_j\\,P(A{=}k\\mid A^*{=}j)=p_k$.\n\n\\emph{Step 4: Closed form and monotonicity.}\n$B(C) = \\lambda\\,V_W/(V_W+\\sigma_\\varepsilon^2)$,\nstructurally identical to confounding (Proposition~\\ref{prop:conf_prop}) with $\\sigma_\\varepsilon^2$ playing the role of $\\sigma_T^2$.\nSince $V_B(\\delta)$ is convex with $V_B'(0)\\leq 0$ (same argument as \\S\\ref{app:monotonicity_proof}, Steps~1--3), $V_W(\\delta)=V{-}V_B(\\delta)$ is non-decreasing under the same conditions on $C_0$.\nSince $h(x)=|\\lambda|x/(x+\\sigma_\\varepsilon^2)$ is increasing, $|B(C(\\delta))|$ is non-decreasing.\n\n\\paragraph{Boundedness of the leakage coefficient.}\n\nThe mediation bias~\\eqref{eq:mediation} writes the residual indirect effect as $(1-\\lambda(C))\\,\\tau_{\\mathrm{ind}}$, which (for $\\tau_{\\mathrm{ind}}\\neq 0$) \\emph{implicitly} defines\n\\begin{equation}\n\\label{eq:lambda_def}\n  \\lambda(C) \\;:=\\; 1-\\frac{B(C)}{\\tau_{\\mathrm{ind}}},\\qquad\n  B(C)\\;\\equiv\\;\\operatorname{plim}\\hat{\\tau}_{\\mathrm{dir}}(A^*)-\\tau_{\\mathrm{dir}},\\quad\n  \\tau_{\\mathrm{ind}}\\;=\\;\\frac{\\operatorname{Cov}(T,f(A))}{\\operatorname{Var}(T)}.\n\\end{equation}\nSubstituting back into~\\eqref{eq:mediation} gives the convex-combination form\n$\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)=\\lambda(C)\\,\\tau_{\\mathrm{dir}}+(1-\\lambda(C))\\,\\tau_{\\mathrm{total}}$, so $\\lambda(C)$ is the weight placing the biased plim between $\\tau_{\\mathrm{dir}}$ (perfect classification) and $\\tau_{\\mathrm{total}}$ (no information).\n\n\\begin{proposition}[Mediation leakage boundedness]\n\\label{prop:lambda_bound}\nLet $\\lambda(C)$ be defined by~\\eqref{eq:lambda_def} with $\\tau_{\\mathrm{ind}}\\neq 0$, and let $C$ be column-stochastic.\n\\begin{enumerate}\n\\item[(a)] $\\lambda(C)\\leq 1$ iff $\\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$ (the bias points in the direction of the indirect effect; no overcorrection).\n\\item[(b)] $\\lambda(C)\\geq 0$ iff additionally $|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$ (the bias does not exceed the indirect effect in magnitude).\n\\end{enumerate}\nEquivalently, $\\lambda(C)\\in[0,1]$ iff $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)\\in[\\min(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}}),\\,\\max(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}})]$.\n\nUnder \\emph{proportional effects} ($f(A)=\\lambda_0\\,g(A)$ with $g(k)=\\mathbb{E}[T\\mid A{=}k]$), both (a) and (b) hold for every $C$, so $\\lambda(C)\\in[0,1]$ unconditionally.\nFor \\emph{general (non-proportional)} $f$, both (a) and (b) can fail because $\\operatorname{Cov}(\\mathbb{E}[g\\mid A^*],\\mathbb{E}[f\\mid A^*])$ may differ in sign or magnitude from $\\operatorname{Cov}(g,f)$ (a covariance-level analogue of Simpson's paradox under $A^*$ aggregation); the numerical verification below quantifies the empirical rate.\nThe endpoints $\\lambda(I)=1$ and $\\lambda(C)\\to 0$ in the rank-one (uninformative) limit hold in all regimes.\n\n\\emph{Sign preservation.} When $\\lambda(C)\\in[0,1]$, the convex-combination form gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)\\in[\\min(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}}),\\,\\max(\\tau_{\\mathrm{dir}},\\tau_{\\mathrm{total}})]$. If additionally $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$, both endpoints share the same sign, so $\\operatorname{sign}(\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{dir}})$ for every~$C$. Under proportional effects, $\\lambda(C)\\in[0,1]$ is automatic (above), so sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ reduces to the single condition $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\n\\end{proposition}\n\n\\begin{proof}\n\\emph{(a),(b).} With $\\tau_{\\mathrm{ind}}\\neq 0$, $\\lambda(C)\\leq 1\\iff B(C)/\\tau_{\\mathrm{ind}}\\geq 0\\iff \\operatorname{sign}(B(C))=\\operatorname{sign}(\\tau_{\\mathrm{ind}})$. Given (a), $\\lambda(C)\\geq 0\\iff B(C)/\\tau_{\\mathrm{ind}}\\leq 1\\iff|B(C)|\\leq|\\tau_{\\mathrm{ind}}|$.\n\n\\emph{Proportional case.} Step~4 of the mediation derivation gives $B(C)=\\lambda_0\\,V_W(C)/(V_W(C)+\\sigma_\\varepsilon^2)$; the rank-one limit $V_W{\\to}V$ yields $\\tau_{\\mathrm{ind}}=\\lambda_0\\,V/(V+\\sigma_\\varepsilon^2)$. Both quantities carry $\\operatorname{sign}(\\lambda_0)$, establishing~(a). The ratio\n\\[\n  \\frac{B(C)}{\\tau_{\\mathrm{ind}}}\\;=\\;\\frac{V_W(C)\\,(V+\\sigma_\\varepsilon^2)}{V\\,(V_W(C)+\\sigma_\\varepsilon^2)}\n\\]\nis monotone increasing in $V_W(C)\\in[0,V]$ with range $[0,1]$ (its derivative in $V_W$ is $\\sigma_\\varepsilon^2(V+\\sigma_\\varepsilon^2)/[V(V_W+\\sigma_\\varepsilon^2)^2]>0$), establishing~(b). Hence $\\lambda(C)\\in[0,1]$ unconditionally.\n\n\\emph{General case.} Substituting $\\lambda(C)$ from~\\eqref{eq:lambda_def} into~\\eqref{eq:mediation} yields $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)=\\lambda(C)\\,\\tau_{\\mathrm{dir}}+(1{-}\\lambda(C))\\,\\tau_{\\mathrm{total}}$, so $\\lambda(C)\\in[0,1]$ iff $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}(C)$ lies in the closed interval with endpoints $\\tau_{\\mathrm{dir}}$ and $\\tau_{\\mathrm{total}}$.\n\n\\emph{Endpoints.} At $C{=}I$, $A^*{=}A$ a.s., $\\mathbb{E}[T\\mid A^*]=g(A)$, and FWL gives $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\tau_{\\mathrm{dir}}$, hence $B(I)=0$ and $\\lambda(I)=1$. At any rank-one $C$ (rows identical), $A^*\\perp A$ so $\\mathbb{E}[T\\mid A^*]$ is constant, the partial regression on $A^*$ has no effect, and $\\operatorname{plim}\\hat\\tau_{\\mathrm{dir}}=\\operatorname{Cov}(Y,T)/\\operatorname{Var}(T)=\\tau_{\\mathrm{total}}$, giving $B=\\tau_{\\mathrm{ind}}$ and $\\lambda=0$.\n\\end{proof}\n\n\\paragraph{Relation to the between-variance ratio.}\nA natural \\emph{diagnostic} closely related to $\\lambda(C)$ is the between-variance ratio\n\\begin{equation}\n\\label{eq:vb_ratio}\n  \\lambda_V(C) \\;:=\\; \\frac{V_B(C)}{V},\\qquad V_B(C)\\;=\\;\\operatorname{Var}\\!\\bigl(\\mathbb{E}[g(A)\\mid A^*]\\bigr),\\quad V\\;=\\;\\operatorname{Var}(g(A)),\n\\end{equation}\nwhich satisfies $\\lambda_V(C)\\in[0,1]$ \\emph{unconditionally} by the law of total variance applied to $g(A)$. Under proportional effects, $\\lambda$ and $\\lambda_V$ agree at the endpoints and are related by\n\\[\n  1-\\lambda(C)\\;=\\;\\frac{V_W(C)\\,(V+\\sigma_\\varepsilon^2)}{V\\,(V_W(C)+\\sigma_\\varepsilon^2)}\\;=\\;\\bigl(1-\\lambda_V(C)\\bigr)\\cdot\\frac{V+\\sigma_\\varepsilon^2}{V_W(C)+\\sigma_\\varepsilon^2},\n\\]\nso they coincide in the limit $\\sigma_\\varepsilon^2\\gg V$. They generally differ for non-proportional $f$. We use $\\lambda$ throughout the main text because it parameterizes~\\eqref{eq:mediation} directly; $\\lambda_V$ remains a useful summary of the channel quality of $A^*$ as a proxy for $A$ (independent of the structural form of $f$).\n\n\\paragraph{Numerical verification.}\nFor each $K\\in\\{3,5,7\\}$ we draw $N{=}10{,}000$ configurations $(\\pi,g,\\sigma_\\varepsilon^2,C)$ with $\\pi\\sim\\operatorname{Dirichlet}(\\mathbf{1})$, $g\\sim\\mathcal{N}(0,I_K)$, $\\sigma_\\varepsilon^2\\sim\\operatorname{Uniform}(0.1,2)$, columns of $C\\sim\\operatorname{Dirichlet}(\\mathbf{1})$, and evaluate $\\lambda(C)$ from~\\eqref{eq:lambda_def} in two regimes for $f$:\n\\begin{itemize}\\itemsep0pt\n\\item \\textbf{Proportional} ($f=\\lambda_0\\,g$, $\\lambda_0\\sim\\mathcal{N}(0,1)\\!\\setminus\\!\\{0\\}$): $\\lambda(C)\\in[0,1]$ in \\emph{all} $30{,}000$ trials (pooled observed range $[1.2{\\times}10^{-5},\\,0.850]$; zero out-of-bounds), confirming the closed-form bound. Sign preservation of $\\hat\\tau_{\\mathrm{dir}}$ therefore reduces to $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$.\n\\item \\textbf{Non-proportional} ($f\\sim\\mathcal{N}(0,I_K)$ drawn independently of $g$, restricted to $|\\tau_{\\mathrm{ind}}|\\geq 0.05$ to avoid the ill-conditioned regime where $\\lambda{=}1{-}B/\\tau_{\\mathrm{ind}}$ diverges): $\\lambda(C)$ exceeds $[0,1]$ in $\\sim15$--$17\\%$ of trials, illustrating that (a) and (b) are not automatic outside the proportional case.\n\\end{itemize}\nThe diagnostic $\\lambda_V(C)$ lies in $[0,1]$ across all $30{,}000$ trials irrespective of regime, as guaranteed by the law of total variance. The script and full results are in \\texttt{artifacts/verify\\_lambda\\_bound.py} and \\texttt{artifacts/verify\\_lambda\\_bound\\_results.json}.\n\n\\subsection{Proof of Theorem~\\ref{thm:k3_symmetric} ($K{=}3$ Symmetric Monotonicity)}\n\\label{app:k3_symmetric_proof}\n\n\\input{k3_symmetric_proof.tex}\n\n\\begin{remark}[Empirical symmetry of LLM confusion matrices]\n\\label{rem:symmetry}\nEmpirical $K{=}3$ confusion matrices from LLM stance detection deviate substantially from symmetry (median relative Frobenius distance $d_{\\mathrm{rel}}{=}0.33$; range 0.30--0.38 across 10 VAST configurations). Theorem~\\ref{thm:k3_symmetric} thus serves as a theoretical anchor establishing that exact monotonicity is achievable at $K{=}3$ under the strongest structural assumption; practical coverage for asymmetric matrices relies on the numerical evidence of Conjecture~\\ref{conj:monotone} ($\\varepsilon < 0.02$ across 545{,}945 adversarial curves including non-symmetric structures).\n\\end{remark}\n\n\\subsection{Collider Topology ($A$ = Collider)}\n\\label{app:collider}\n\n\\paragraph{Data-generating process.}\n$T\\to A\\leftarrow Y$, $T\\to Y$.\nThe treatment effect is unconfounded:\n\\begin{align*}\n  T &\\sim \\mathcal{N}(0,1),\\quad\n  Y = \\tau\\,T + \\varepsilon_Y,\\quad \\varepsilon_Y\\sim\\mathcal{N}(0,1),\\;\\varepsilon_Y\\perp T,\\\\\n  A\\mid T,Y &\\sim \\operatorname{Categorical}\\bigl(\\operatorname{softmax}(\\boldsymbol{\\delta}_T\\,T + \\boldsymbol{\\delta}_Y\\,Y)\\bigr).\n\\end{align*}\nThe collider $A$ is a common \\emph{effect} of $T$ and $Y$.\nThe no-control estimator (regressing $Y$ on $T$ alone) is consistent: $\\operatorname{plim}\\hat\\tau_{\\mathrm{nc}}=\\tau$.\nThe researcher erroneously controls for $A^*$, inducing Berkson's bias.\n\n\\paragraph{Bias decomposition.}\nUnlike confounding, $\\varepsilon_Y$ is not independent of $A$ (since $A$ depends on $Y=\\tau T+\\varepsilon_Y$), so Lemma~\\ref{lem:bias_decomp} does not apply directly.\nInstead, we derive the bias from the FWL identity~\\eqref{eq:fwl}.\nWriting $\\tilde{Y}=\\tau\\tilde{T}+(\\varepsilon_Y-\\mathbb{E}[\\varepsilon_Y\\mid A^*])$ and noting that $\\mathbb{E}[\\tilde{T}\\,\\varepsilon_Y]=\\mathbb{E}[\\operatorname{Cov}(T,\\varepsilon_Y\\mid A^*)]$ (since $T\\perp\\varepsilon_Y$ unconditionally):\n\\begin{equation}\n  \\operatorname{plim}\\hat\\tau(C) = \\tau + B(C),\\quad\n  B(C) = \\frac{\\mathbb{E}[\\operatorname{Cov}(T,\\,\\varepsilon_Y\\mid A^*)]}{\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]}.\n  \\label{eq:bias_col}\n\\end{equation}\nUnder non-differential misclassification ($A^*\\perp(T,\\varepsilon_Y)\\mid A$), define $g(k)=\\mathbb{E}[T\\mid A{=}k]$ and $h(k)=\\mathbb{E}[\\varepsilon_Y\\mid A{=}k]$.\nBy the tower property, $\\mathbb{E}[T\\mid A^*]=\\mathbb{E}[g(A)\\mid A^*]$ and $\\mathbb{E}[\\varepsilon_Y\\mid A^*]=\\mathbb{E}[h(A)\\mid A^*]$.\nSince $\\operatorname{Cov}(T,\\varepsilon_Y)=0$, the law of total covariance gives:\n\\[\n  B(C) = \\frac{-\\operatorname{Cov}\\bigl(\\mathbb{E}[g(A)\\mid A^*],\\;\\mathbb{E}[h(A)\\mid A^*]\\bigr)}{\\mathbb{E}[\\operatorname{Var}(T\\mid A^*)]}.\n\\]\n\n\\paragraph{Endpoint analysis.}\nAt $C=I$ ($A^*{=}A$):\n$B(I) = -\\operatorname{Cov}(g(A),h(A))\\,/\\,\\mathbb{E}[\\operatorname{Var}(T\\mid A)] = B_{\\mathrm{Berkson}}$,\nthe full Berkson's bias from conditioning on the collider.\n\nAt $C=\\frac{1}{K}\\mathbf{1}\\mathbf{1}^\\top$ ($A^*\\perp A$):\n$\\mathbb{E}[g(A)\\mid A^*]$ and $\\mathbb{E}[h(A)\\mid A^*]$ are constant, so $B=0$ and $\\operatorname{plim}\\hat\\tau=\\tau$.\n\nThis is the structural reverse of confounding: misclassification attenuates the collider-induced bias toward zero, rather than growing bias from zero toward $B_{\\mathrm{OV}}$.\n\n\\begin{proposition}[Collider sign preservation --- proportional case]",
      "numLines": 150,
      "startLine": 400,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "745735b2-7584-4a75-aa6c-1020ffe626e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 71 · 2026-05-24T06:37:17.360Z_

<details open><summary>🔧 Tool call — Read · `toolu_01P5ev9KR6Wx7k9Fs277t5AR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 550,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1f8b79bb-c3bc-453f-ad6c-2bec0d0b06b0",
  "isSidechain": false,
  "requestId": "req_011CbLvwvQgvQBtz9tpEKbR1",
  "type": "assistant",
  "uuid": "4b792006-d419-4e4d-b42d-90e795c7077c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AKVMaUPAMGdh4mPtfBLzZa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4664,
      "cache_read_input_tokens": 60058,
      "output_tokens": 2599,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4664,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2599,
          "cache_read_input_tokens": 60058,
          "cache_creation_input_tokens": 4664,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4664
          },
          "type": "message"
        }
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
  "leafUuid": "003bf7a7-60a5-4bf8-b56c-499c13e3106f",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 73_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 74 · 2026-05-24T06:37:21.490Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me continue reading the appendix to look for formula duplications with the main text. Let me also read the remaining sections.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "003bf7a7-60a5-4bf8-b56c-499c13e3106f",
  "isSidechain": false,
  "requestId": "req_011CbLw2FnNhE1EQYa5mz3Bt",
  "type": "assistant",
  "uuid": "c376c442-51b6-45bc-a872-8319da806d33",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGBa2ojPZQengvBfyUG2sB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21464,
      "cache_read_input_tokens": 64722,
      "output_tokens": 360,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 360,
          "cache_read_input_tokens": 64722,
          "cache_creation_input_tokens": 21464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21464
          },
          "type": "message"
        }
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

_source line 75 · 2026-05-24T06:37:22.464Z_

Now let me collect all labeled equations from main text and check for duplicates in the appendix. Let me also read more of the appendix.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c376c442-51b6-45bc-a872-8319da806d33",
  "isSidechain": false,
  "requestId": "req_011CbLw2FnNhE1EQYa5mz3Bt",
  "type": "assistant",
  "uuid": "8a873ef1-08ef-4fe9-8672-1153a91665a6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGBa2ojPZQengvBfyUG2sB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21464,
      "cache_read_input_tokens": 64722,
      "output_tokens": 360,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 360,
          "cache_read_input_tokens": 64722,
          "cache_creation_input_tokens": 21464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21464
          },
          "type": "message"
        }
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

_source line 76 · 2026-05-24T06:37:25.850Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01SCeynC1ry1tUAYpjEKFF8o`</summary>

```json
{
  "pattern": "\\\\label\\{eq:",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "output_mode": "content",
  "-n": true,
  "glob": "*.tex",
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8a873ef1-08ef-4fe9-8672-1153a91665a6",
  "isSidechain": false,
  "requestId": "req_011CbLw2FnNhE1EQYa5mz3Bt",
  "type": "assistant",
  "uuid": "6c3f9128-81eb-46e9-bbda-71f1969cdb08",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGBa2ojPZQengvBfyUG2sB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21464,
      "cache_read_input_tokens": 64722,
      "output_tokens": 360,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 360,
          "cache_read_input_tokens": 64722,
          "cache_creation_input_tokens": 21464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21464
          },
          "type": "message"
        }
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

_source line 77 · 2026-05-24T06:37:26.617Z_

<details><summary>↩ Tool result · `toolu_01R5Mu8sCwjB1rAZJSaBVtZ8`</summary>

```text
750	\midrule
751	Mediation & $\operatorname{sign}(\tau_{\mathrm{dir}})=\operatorname{sign}(\tau_{\mathrm{total}})$ & Empirical & $\checkmark$ ($0.5$ vs $0.85$)\\
752	M-bias & Bias is attenuating (toward $\tau$) & Empirical & $\checkmark$ \\
753	Front-door & $\operatorname{sign}(\lambda\alpha_U)=\operatorname{sign}(\lambda\alpha_U{+}\operatorname{Cov}(T,f))$ & Empirical & $\checkmark$ ($0.50$ vs $0.80$)\\
754	\midrule
755	Exposure & Not guaranteed for $K\geq 3$ & Counterex. & See §\ref{app:exposure} \\
756	IV & Not guaranteed (denominator instability) & --- & --- \\
757	\bottomrule
758	\end{tabular}
759	\caption{Sufficient conditions for sign preservation under non-differential misclassification.
760	``Proved'' = algebraic proof via Cauchy--Schwarz (confounding) or Berkson attenuation (collider).
761	``Empirical'' = verified across 100{,}000 random column-stochastic matrices with zero violations; analytic proof for general $K$ remains open.
762	All conditions are on DGP parameters (not on $C$): once satisfied, sign preservation holds for all column-stochastic $C$ with $C_{kk}>0$.}
763	\label{tab:sign_conditions}
764	\end{table}
765	
766	\paragraph{Structural argument for M-bias topology.}
767	\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.
768	Misclassification of $A$ weakens the statistical association along this backdoor path, reducing the spurious correlation rather than amplifying it.
769	The bias therefore interpolates between the full M-bias (perfect classification, $\delta{=}0$) and zero (no classification information, $\delta{\to}\delta_{\max}$), monotonically non-increasing in $\delta$.
770	
771	\paragraph{M-bias sign-flip ASV $= \infty$.}
772	For the four covariate topologies (confounding, mediation, collider, M-bias), FWL invariance (Appendix~\ref{app:fwl}) implies that the coefficient on $T$ depends on $A^*$ only through the residualized relationship $\tilde{T} = T - \mathbb{E}[T \mid A^*]$. For M-bias, the spurious path through $A$ is the sole source of bias, and misclassification attenuates this path for all column-stochastic $C$. Since $\text{bias}(C(\delta))$ is monotonically non-increasing in $\delta$ and starts at a value with the same sign as $\tau$, no $\delta \in [0, \delta_{\max}]$ can produce a sign reversal. Therefore $\delta^*_{\text{sign}} = \infty$, which is a direct consequence of FWL invariance combined with the protective monotonicity of M-bias misclassification.
773	
774	\paragraph{Remark.}
775	The sign preservation conditions for confounding, mediation, collider, and front-door are conditions on the DGP parameters (the relative strength of the causal effect versus the confounding, indirect, or collider-induced bias), not on the confusion matrix $C$.
776	Once the condition is satisfied, sign preservation holds for \emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.
777	Conversely, if the condition fails (i.e., the omitted-variable or total-effect estimate has the opposite sign from $\tau$), then there exist confusion matrices that produce sign reversal.
778	For the DGP parameters used throughout our experiments, the conditions are comfortably satisfied.
779	The sign-alignment condition is violated when the confounder has opposing effects on treatment and outcome (e.g., $\gamma_A > 0$ on $T$ but $\gamma_A < 0$ on $Y$), producing $\operatorname{sign}(\tau) \neq \operatorname{sign}(\tau_{\mathrm{OV}})$. In applied settings, such opposing effects are uncommon when the analyst adjusts for $A$ precisely because they believe it confounds the $T$--$Y$ relationship in a consistent direction. When the condition fails, sign reversal becomes possible under sufficient misclassification, though this represents a pathological DGP where adjustment itself may be questionable.
780	
781	\subsection{Adversarial Monotonicity Verification}
782	\label{app:adversarial_monotonicity}
783	
784	We test Conjecture~\ref{conj:monotone} under four adversarial confusion matrix structures designed to challenge envelope monotonicity: near-permutation ($C_0 = (1{-}\epsilon)P + \epsilon \cdot \mathbf{1}\mathbf{1}^\top/K$, $P$ a random permutation), block-diagonal (within-block confusion only), sparse (two nonzero entries per column), and near-uniform ($C_{kk} \to 1/K$). For each structure, we sweep $\delta \in [0,1]$ along $C(\delta) = (1{-}\delta)I + \delta C_0$ and measure the maximum single-step monotonicity violation $\varepsilon_{\mathrm{abs}}$.
785	
786	\begin{table}[h]
787	\centering
788	\small
789	\caption{Adversarial monotonicity test across $K{=}3,5,7$, seven topologies, and three $\beta$ configurations ($N{=}1{,}000$ matrices per cell, 545{,}945 total curves).}
790	\label{tab:adversarial_monotonicity}
791	\begin{tabular}{lcc}
792	\toprule
793	\textbf{Structure} & \textbf{Non-monotone \%} & \textbf{Max $\varepsilon_{\mathrm{abs}}$} \\
794	\midrule
795	Near-permutation & 35.4\% & 0.016 \\
796	Block-diagonal & 0\% & 0 \\
797	Sparse & 2.3\% & 0.003 \\
798	Near-uniform & 0\% & 0 \\
799	\midrule
800	\textbf{All structures} & 11.9\% & \textbf{0.016} \\
801	\bottomrule
802	\end{tabular}
803	\end{table}
804	
805	The four families span the extremes of the column-stochastic polytope: diagonal-dominant (near-identity), maximally reordered (near-permutation), degenerate (rank-deficient sparse), and block-structured heterogeneity (block-diagonal). The global maximum violation $\varepsilon_{\mathrm{abs}} = 0.016 < 0.02$ confirms that Conjecture~\ref{conj:monotone} holds under adversarial matrix structures. Near-permutation matrices with alternating-sign $\beta$ coefficients represent the most challenging case; even here, violations remain below the conjectured bound. Block-diagonal and near-uniform structures show exact monotonicity.
806	
807	\section{Supplementary Tables, Figures, and Algorithm}
808	\label{app:supplementary}
809	
810	\subsection{Binarization Collapse}
811	\label{app:binarization}
812	
813	Collapsing $K$-class annotations to binary before analysis discards multi-class error structure. We quantify ``binarization collapse'' as $\Delta = |\text{bias}_{K} - \text{bias}_{K \to 2}|$.
814	
815	For $K{=}3$, binarization introduces additional bias varying $>$150$\times$ across topologies: from $\bar{\Delta}{=}0.006$ (M-bias) to $\bar{\Delta}{=}0.926$ (IV). Exposure and IV also introduce sign flips during binarization (14\% and 17.5\%), a phenomenon absent in the other topologies (Figure~\ref{fig:binarization}).
816	
817	
818	\begin{table}[h]
819	\centering
820	\caption{ASV type applicability and sensitivity across DAG topologies. Magnitude ASV at $\tau{=}0.5$, 10\% threshold. Power at $\tau{=}0.05$ significance filter. ---: not applicable.}
821	\label{tab:asv_grid}
822	\small
823	\begin{tabular}{lcccl}
824	\toprule
825	\textbf{Topology} & \textbf{Mag. ASV} & \textbf{Signif.} & \textbf{Sign-flip} & \textbf{Rank} \\
826	\midrule
827	IV & 0.101--0.607 & 0\% & 1.1--6.7 & 1 (fragile) \\
828	Front-door & 0.064--0.387 & 100\% & --- & 2 \\
829	Confounding & 0.081--0.487 & 100\% & --- & 3 \\
830	Mediation & 0.076--0.454 & 0\% & --- & 4 \\
831	Collider & 0.338--2.028 & 0\% & --- & 5 \\
832	M-bias & $\infty$ & 96--100\% & --- & 6 (immune) \\
833	Exposure & --- & --- & 83.4\%$^*$ & --- \\
834	\bottomrule
835	\multicolumn{5}{l}{\scriptsize $^*$Fraction of $C_0$ with $\tau_{\text{sign\_flip}} < 1$. Exposure uses sign-flip ASV exclusively.}
836	\end{tabular}
837	\end{table}
838	
839	\begin{figure}[h]
840	\centering
841	\includegraphics[width=\columnwidth]{fig7_dirichlet_overlay.pdf}
842	\caption{Empirical LLM confusion matrices overlaid on theoretical violation-rate curves (exposure, left; IV, right). Theoretical curves are derived from $K{=}3$ Dirichlet random matrices; empirical points are positioned at their minimum diagonal entry. Markers denote datasets (circles: HumAID $K{=}10$; squares: VAST $K{=}3$; triangles: CivilComments $K{=}2$).}
843	\label{fig:dirichlet_overlay}
844	\end{figure}
845	
846	\begin{figure}[h]
847	\centering
848	\includegraphics[width=\columnwidth]{fig4_binarization.pdf}
849	\caption{Binarization collapse $\Delta$ across topologies. Collapsing $K{=}3$ annotations to binary introduces additional bias varying $>$150$\times$ from M-bias (0.006) to IV (0.926).}
850	\label{fig:binarization}
851	\end{figure}
852	
853	\begin{figure}[h]
854	\centering
855	\includegraphics[width=\columnwidth]{fig6_asv_heatmap.pdf}
856	\caption{ASV magnitude ranges across topologies for HumAID ($K{=}10$). Left: magnitude ASV ($\delta^*$) range across 8 LLM configurations; lower values indicate greater fragility. ``Safe'' topologies never exceed the 10\% bias threshold. Right: percentage of configurations flagged as ASV-unsafe.}
857	\label{fig:asv_heatmap}
858	\end{figure}
859	
860	\begin{table}[h]
861	\centering
862	\caption{RMSE reduction (\%) by correction method and DAG topology (mean across 6 error structures, $N_{\text{sim}}{=}1{,}000$). Positive = reduced RMSE; negative = increased RMSE. Naive/MLA show 0.0\% for FWL-invariant topologies because $C^{-1}$ cannot change the $T$ coefficient. \textbf{Bold}: best method per topology; \underline{underline}: best gold-free method.}
863	\label{tab:correction}
864	\small
865	\begin{tabular}{lccccc}
866	\toprule
867	\textbf{Topology} & \textbf{Naive} & \textbf{MLA} & \textbf{DSL} & \textbf{SIMEX} & \textbf{PPI++} \\
868	\midrule
869	Confounding & 0.0 & 0.0 & \underline{48.0} & 35.1 & \textbf{83.2} \\
870	Mediation & 0.0 & 0.0 & \underline{52.9} & 39.1 & \textbf{54.1} \\
871	Collider & 0.0 & 0.0 & $-$92.6 & \underline{31.8} & \textbf{50.5} \\
872	M-bias & 0.0 & 0.0 & $-$267 & \textbf{\underline{0.1}} & $-$88.0 \\
873	\midrule
874	Front-door & $-$52.7 & $-$111.5 & \underline{$-$29.0} & $-$62.4 & \textbf{74.1} \\
875	Exposure & $-$44.8 & $-$89.0 & $-$59.5 & \underline{$-$9.8} & \textbf{75.5} \\
876	IV & $-$40.4 & $-$58.7 & $-$206.1 & \underline{59.4} & \textbf{79.4} \\
877	\midrule
878	Grand mean & $-$19.7 & $-$37.0 & $-$79.0 & 13.3 & \textbf{47.0} \\
879	\bottomrule
880	\end{tabular}
881	\end{table}
882	
883	\paragraph{Error structures used in correction experiments.}
884	The six confusion matrix structures used for Table~\ref{tab:correction} are:
885	(1)~\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;
886	(2)~\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;
887	(3)~\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;
888	(4)~\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);
889	(5)~\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;
890	(6)~\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.
891	All are column-stochastic with $K{=}3$. Results are averaged across all six structures.
892	
893	\begin{algorithm}[h]
894	\caption{Correction method selection for LLM-annotated causal inference. This topology-based classification is robust to $\varepsilon$-approximate deviations; practitioners computing quantitative ASV thresholds should note the $\varepsilon$-approximate bounds (Conjecture~\ref{conj:monotone}, Section~\ref{sec:asv}). Assumes linear structural equations; FWL-based routing may not apply under nonlinear models (see Appendix~\ref{sec:logistic_dgp}). Thresholds calibrated for $K{=}3$ linear SEM; recalibrate for different $K$ using topology-specific bias functions.}
895	\label{alg:correction}
896	\small
897	\begin{algorithmic}[1]
898	\REQUIRE DAG topology $\mathcal{T}$, gold-label availability $G \in \{\textsc{yes}, \textsc{no}\}$
899	\ENSURE Recommended method $M$, risk level $R$
900	\STATE
901	\STATE \textbf{Step 0: DAG uncertainty} \COMMENT{If $\mathcal{T}$ is uncertain, repeat Steps 1--3 under each candidate topology and report the range}
902	\STATE
903	\STATE \textbf{Step 1: Assess risk level}
904	\IF{$\mathcal{T} \in \{\text{M-bias}\}$}
905	    \STATE $R \gets \textsc{Low}$ \COMMENT{$|\text{bias}| < 0.04$ for all $C$}
906	\ELSIF{$\mathcal{T} \in \{\text{Conf., Med., Coll., Front-door}\}$}
907	    \STATE $R \gets \textsc{Medium}$ \COMMENT{bounded bias, no sign reversal}
908	\ELSE
909	    \STATE $R \gets \textsc{High}$ \COMMENT{Exposure, IV: sign reversal 83.4\% / 52.6\%}
910	\ENDIF
911	\STATE
912	\STATE \textbf{Step 2: Select correction method}
913	\IF{$G = \textsc{yes}$}
914	    \IF{$\mathcal{T} = \text{M-bias}$}
915	        \STATE $M \gets \textsc{None}$ \COMMENT{PPI++ RMSE red.\ $-$88.0\%; no correction preferred}
916	    \ELSE
917	        \STATE $M \gets \text{PPI++}$ \COMMENT{47.0\% RMSE red., 96.8\% coverage}
918	    \ENDIF
919	\ELSE
920	    \STATE \COMMENT{no gold labels}
921	    \IF{$\mathcal{T} \in \{\text{Confounding, Mediation}\}$}
922	        \STATE $M \gets \text{DSL}$ \COMMENT{48.0\% / 52.9\% RMSE reduction}
923	    \ELSIF{$\mathcal{T} = \text{IV}$}
924	        \STATE $M \gets \text{MC-SIMEX}$ \COMMENT{59.4\% RMSE reduction}
925	    \ELSIF{$\mathcal{T} \in \{\text{Collider, M-bias}\}$}
926	        \STATE $M \gets \text{MC-SIMEX}$ \COMMENT{31.8\% / 0.1\% RMSE reduction}
927	    \ELSE
928	        \STATE $M \gets \emptyset$; flag: acquire gold labels \COMMENT{no reliable gold-free method}
929	    \ENDIF
930	\ENDIF
931	\STATE
932	\STATE \textbf{Step 3: FWL invariance warning}
933	\IF{$\mathcal{T} \in \{\text{Conf., Med., Coll., M-bias}\}$}
934	    \STATE Skip Naive plug-in and MLA \COMMENT{0\% bias red.\ on $T$ coeff.\ (Table~\ref{tab:correction}: below 2\%, no method improves)}
935	\ENDIF
936	\RETURN $(M, R)$
937	\end{algorithmic}
938	\end{algorithm}
939	
940	\subsection{Proof of FWL Invariance}
941	\label{app:fwl_proof}
942	
943	For the four topologies where $A$ enters as a covariate (confounding, mediation, collider, M-bias), the regression is $Y = \tau T + \boldsymbol{\gamma}^\top \mathbf{D}^* + \varepsilon$, where $\mathbf{D}^*$ is the $N \times (K{-}1)$ dummy matrix for $A^*$. Any matrix-based correction replaces $\mathbf{D}^*$ with $\tilde{\mathbf{D}} = \mathbf{D}^* M$ for some invertible $(K{-}1) \times (K{-}1)$ matrix $M$ (e.g., $M = C^{-1}$ for plug-in, or $M = (C^\top C)^{-1} C^\top$ for MLE). By the Frisch--Waugh--Lovell theorem~\cite{lovell1963}, $\hat{\tau}$ depends only on the residual of $T$ projected off $\operatorname{col}(\mathbf{D}^*)$. Since $\operatorname{col}(\mathbf{D}^* M) = \operatorname{col}(\mathbf{D}^*)$ for invertible $M$, the projection is unchanged and $\hat{\tau}(\tilde{\mathbf{D}}) = \hat{\tau}(\mathbf{D}^*)$ exactly. SIMEX adds noise $\mathbf{D}^*_{\text{sim}} = \mathbf{D}^* + \lambda \mathbf{E}$; when $\mathbf{E}$ is generated from the same column space, the extrapolation to $\lambda = -1$ converges to a column-space-equivalent transformation, yielding 0\% bias reduction empirically.
944	
945	\paragraph{FWL breakdown under logistic regression.}
946	\label{sec:fwl_logistic}
947	The column-space argument applies only to estimators whose treatment coefficient is a function of $T$ residualized off $\operatorname{col}(\mathbf{D}^*)$---a property of linear projection. The logistic MLE solves $\sum_i (Y_i - \sigma(\mathbf{x}_i^\top\boldsymbol{\beta}))\mathbf{x}_i = \mathbf{0}$; the implicit weighting by $\sigma'(\cdot)$ depends on the actual values of the design columns, not only on their span, so replacing $\mathbf{D}^*$ by $\mathbf{D}^* M$ generally changes the fitted $\hat\tau$. We verify this on the confounding topology ($K{=}3$, $\tau{=}0.5$, $N{=}10{,}000\times 500$ MC reps) under both linear ($Y = \tau T + \mathbf{D}\boldsymbol{\beta}+\varepsilon$) and logistic ($Y\sim\mathrm{Bern}(\sigma(\tau T + \mathbf{D}\boldsymbol{\beta}))$) DGPs, comparing the uncorrected estimator (fit on $\mathbf{D}^*$) against Naive plug-in (fit on per-sample $(C^{-1}\mathbf{e}_{A^*})_{1:K}$). Per-rep estimates are paired (same $A^*$, same outcome).
948	
949	\begin{table}[h]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cc10219f-f601-4250-ac1b-92f5e866a0c7",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "6cf412c7-56b2-4ae9-ba59-cdad0f7062fd",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\midrule\nMediation & $\\operatorname{sign}(\\tau_{\\mathrm{dir}})=\\operatorname{sign}(\\tau_{\\mathrm{total}})$ & Empirical & $\\checkmark$ ($0.5$ vs $0.85$)\\\\\nM-bias & Bias is attenuating (toward $\\tau$) & Empirical & $\\checkmark$ \\\\\nFront-door & $\\operatorname{sign}(\\lambda\\alpha_U)=\\operatorname{sign}(\\lambda\\alpha_U{+}\\operatorname{Cov}(T,f))$ & Empirical & $\\checkmark$ ($0.50$ vs $0.80$)\\\\\n\\midrule\nExposure & Not guaranteed for $K\\geq 3$ & Counterex. & See §\\ref{app:exposure} \\\\\nIV & Not guaranteed (denominator instability) & --- & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Sufficient conditions for sign preservation under non-differential misclassification.\n``Proved'' = algebraic proof via Cauchy--Schwarz (confounding) or Berkson attenuation (collider).\n``Empirical'' = verified across 100{,}000 random column-stochastic matrices with zero violations; analytic proof for general $K$ remains open.\nAll conditions are on DGP parameters (not on $C$): once satisfied, sign preservation holds for all column-stochastic $C$ with $C_{kk}>0$.}\n\\label{tab:sign_conditions}\n\\end{table}\n\n\\paragraph{Structural argument for M-bias topology.}\n\\emph{M-bias:} The M-structure creates a backdoor path through two latent common causes.\nMisclassification of $A$ weakens the statistical association along this backdoor path, reducing the spurious correlation rather than amplifying it.\nThe bias therefore interpolates between the full M-bias (perfect classification, $\\delta{=}0$) and zero (no classification information, $\\delta{\\to}\\delta_{\\max}$), monotonically non-increasing in $\\delta$.\n\n\\paragraph{M-bias sign-flip ASV $= \\infty$.}\nFor the four covariate topologies (confounding, mediation, collider, M-bias), FWL invariance (Appendix~\\ref{app:fwl}) implies that the coefficient on $T$ depends on $A^*$ only through the residualized relationship $\\tilde{T} = T - \\mathbb{E}[T \\mid A^*]$. For M-bias, the spurious path through $A$ is the sole source of bias, and misclassification attenuates this path for all column-stochastic $C$. Since $\\text{bias}(C(\\delta))$ is monotonically non-increasing in $\\delta$ and starts at a value with the same sign as $\\tau$, no $\\delta \\in [0, \\delta_{\\max}]$ can produce a sign reversal. Therefore $\\delta^*_{\\text{sign}} = \\infty$, which is a direct consequence of FWL invariance combined with the protective monotonicity of M-bias misclassification.\n\n\\paragraph{Remark.}\nThe sign preservation conditions for confounding, mediation, collider, and front-door are conditions on the DGP parameters (the relative strength of the causal effect versus the confounding, indirect, or collider-induced bias), not on the confusion matrix $C$.\nOnce the condition is satisfied, sign preservation holds for \\emph{all} column-stochastic $C$ with $C_{kk}>0$---no diagonal-dominance restriction is needed.\nConversely, if the condition fails (i.e., the omitted-variable or total-effect estimate has the opposite sign from $\\tau$), then there exist confusion matrices that produce sign reversal.\nFor the DGP parameters used throughout our experiments, the conditions are comfortably satisfied.\nThe sign-alignment condition is violated when the confounder has opposing effects on treatment and outcome (e.g., $\\gamma_A > 0$ on $T$ but $\\gamma_A < 0$ on $Y$), producing $\\operatorname{sign}(\\tau) \\neq \\operatorname{sign}(\\tau_{\\mathrm{OV}})$. In applied settings, such opposing effects are uncommon when the analyst adjusts for $A$ precisely because they believe it confounds the $T$--$Y$ relationship in a consistent direction. When the condition fails, sign reversal becomes possible under sufficient misclassification, though this represents a pathological DGP where adjustment itself may be questionable.\n\n\\subsection{Adversarial Monotonicity Verification}\n\\label{app:adversarial_monotonicity}\n\nWe test Conjecture~\\ref{conj:monotone} under four adversarial confusion matrix structures designed to challenge envelope monotonicity: near-permutation ($C_0 = (1{-}\\epsilon)P + \\epsilon \\cdot \\mathbf{1}\\mathbf{1}^\\top/K$, $P$ a random permutation), block-diagonal (within-block confusion only), sparse (two nonzero entries per column), and near-uniform ($C_{kk} \\to 1/K$). For each structure, we sweep $\\delta \\in [0,1]$ along $C(\\delta) = (1{-}\\delta)I + \\delta C_0$ and measure the maximum single-step monotonicity violation $\\varepsilon_{\\mathrm{abs}}$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Adversarial monotonicity test across $K{=}3,5,7$, seven topologies, and three $\\beta$ configurations ($N{=}1{,}000$ matrices per cell, 545{,}945 total curves).}\n\\label{tab:adversarial_monotonicity}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Structure} & \\textbf{Non-monotone \\%} & \\textbf{Max $\\varepsilon_{\\mathrm{abs}}$} \\\\\n\\midrule\nNear-permutation & 35.4\\% & 0.016 \\\\\nBlock-diagonal & 0\\% & 0 \\\\\nSparse & 2.3\\% & 0.003 \\\\\nNear-uniform & 0\\% & 0 \\\\\n\\midrule\n\\textbf{All structures} & 11.9\\% & \\textbf{0.016} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe four families span the extremes of the column-stochastic polytope: diagonal-dominant (near-identity), maximally reordered (near-permutation), degenerate (rank-deficient sparse), and block-structured heterogeneity (block-diagonal). The global maximum violation $\\varepsilon_{\\mathrm{abs}} = 0.016 < 0.02$ confirms that Conjecture~\\ref{conj:monotone} holds under adversarial matrix structures. Near-permutation matrices with alternating-sign $\\beta$ coefficients represent the most challenging case; even here, violations remain below the conjectured bound. Block-diagonal and near-uniform structures show exact monotonicity.\n\n\\section{Supplementary Tables, Figures, and Algorithm}\n\\label{app:supplementary}\n\n\\subsection{Binarization Collapse}\n\\label{app:binarization}\n\nCollapsing $K$-class annotations to binary before analysis discards multi-class error structure. We quantify ``binarization collapse'' as $\\Delta = |\\text{bias}_{K} - \\text{bias}_{K \\to 2}|$.\n\nFor $K{=}3$, binarization introduces additional bias varying $>$150$\\times$ across topologies: from $\\bar{\\Delta}{=}0.006$ (M-bias) to $\\bar{\\Delta}{=}0.926$ (IV). Exposure and IV also introduce sign flips during binarization (14\\% and 17.5\\%), a phenomenon absent in the other topologies (Figure~\\ref{fig:binarization}).\n\n\n\\begin{table}[h]\n\\centering\n\\caption{ASV type applicability and sensitivity across DAG topologies. Magnitude ASV at $\\tau{=}0.5$, 10\\% threshold. Power at $\\tau{=}0.05$ significance filter. ---: not applicable.}\n\\label{tab:asv_grid}\n\\small\n\\begin{tabular}{lcccl}\n\\toprule\n\\textbf{Topology} & \\textbf{Mag. ASV} & \\textbf{Signif.} & \\textbf{Sign-flip} & \\textbf{Rank} \\\\\n\\midrule\nIV & 0.101--0.607 & 0\\% & 1.1--6.7 & 1 (fragile) \\\\\nFront-door & 0.064--0.387 & 100\\% & --- & 2 \\\\\nConfounding & 0.081--0.487 & 100\\% & --- & 3 \\\\\nMediation & 0.076--0.454 & 0\\% & --- & 4 \\\\\nCollider & 0.338--2.028 & 0\\% & --- & 5 \\\\\nM-bias & $\\infty$ & 96--100\\% & --- & 6 (immune) \\\\\nExposure & --- & --- & 83.4\\%$^*$ & --- \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize $^*$Fraction of $C_0$ with $\\tau_{\\text{sign\\_flip}} < 1$. Exposure uses sign-flip ASV exclusively.}\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig7_dirichlet_overlay.pdf}\n\\caption{Empirical LLM confusion matrices overlaid on theoretical violation-rate curves (exposure, left; IV, right). Theoretical curves are derived from $K{=}3$ Dirichlet random matrices; empirical points are positioned at their minimum diagonal entry. Markers denote datasets (circles: HumAID $K{=}10$; squares: VAST $K{=}3$; triangles: CivilComments $K{=}2$).}\n\\label{fig:dirichlet_overlay}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig4_binarization.pdf}\n\\caption{Binarization collapse $\\Delta$ across topologies. Collapsing $K{=}3$ annotations to binary introduces additional bias varying $>$150$\\times$ from M-bias (0.006) to IV (0.926).}\n\\label{fig:binarization}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig6_asv_heatmap.pdf}\n\\caption{ASV magnitude ranges across topologies for HumAID ($K{=}10$). Left: magnitude ASV ($\\delta^*$) range across 8 LLM configurations; lower values indicate greater fragility. ``Safe'' topologies never exceed the 10\\% bias threshold. Right: percentage of configurations flagged as ASV-unsafe.}\n\\label{fig:asv_heatmap}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{RMSE reduction (\\%) by correction method and DAG topology (mean across 6 error structures, $N_{\\text{sim}}{=}1{,}000$). Positive = reduced RMSE; negative = increased RMSE. Naive/MLA show 0.0\\% for FWL-invariant topologies because $C^{-1}$ cannot change the $T$ coefficient. \\textbf{Bold}: best method per topology; \\underline{underline}: best gold-free method.}\n\\label{tab:correction}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Naive} & \\textbf{MLA} & \\textbf{DSL} & \\textbf{SIMEX} & \\textbf{PPI++} \\\\\n\\midrule\nConfounding & 0.0 & 0.0 & \\underline{48.0} & 35.1 & \\textbf{83.2} \\\\\nMediation & 0.0 & 0.0 & \\underline{52.9} & 39.1 & \\textbf{54.1} \\\\\nCollider & 0.0 & 0.0 & $-$92.6 & \\underline{31.8} & \\textbf{50.5} \\\\\nM-bias & 0.0 & 0.0 & $-$267 & \\textbf{\\underline{0.1}} & $-$88.0 \\\\\n\\midrule\nFront-door & $-$52.7 & $-$111.5 & \\underline{$-$29.0} & $-$62.4 & \\textbf{74.1} \\\\\nExposure & $-$44.8 & $-$89.0 & $-$59.5 & \\underline{$-$9.8} & \\textbf{75.5} \\\\\nIV & $-$40.4 & $-$58.7 & $-$206.1 & \\underline{59.4} & \\textbf{79.4} \\\\\n\\midrule\nGrand mean & $-$19.7 & $-$37.0 & $-$79.0 & 13.3 & \\textbf{47.0} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Error structures used in correction experiments.}\nThe six confusion matrix structures used for Table~\\ref{tab:correction} are:\n(1)~\\emph{Diagonal-dominant}: $C_{kk}{=}0.7$, off-diagonal uniform;\n(2)~\\emph{Moderate noise}: $C_{kk}{=}0.5$, off-diagonal uniform;\n(3)~\\emph{Near-permutation}: $C_{kk}{=}0.4$, largest off-diagonal 0.5;\n(4)~\\emph{Asymmetric}: $C_{kk}$ varies (0.8, 0.5, 0.3);\n(5)~\\emph{Block confusion}: two classes confused ($C_{12}{=}C_{21}{=}0.4$), third clean;\n(6)~\\emph{Heavy noise}: $C_{kk}{=}0.4$, off-diagonal uniform.\nAll are column-stochastic with $K{=}3$. Results are averaged across all six structures.\n\n\\begin{algorithm}[h]\n\\caption{Correction method selection for LLM-annotated causal inference. This topology-based classification is robust to $\\varepsilon$-approximate deviations; practitioners computing quantitative ASV thresholds should note the $\\varepsilon$-approximate bounds (Conjecture~\\ref{conj:monotone}, Section~\\ref{sec:asv}). Assumes linear structural equations; FWL-based routing may not apply under nonlinear models (see Appendix~\\ref{sec:logistic_dgp}). Thresholds calibrated for $K{=}3$ linear SEM; recalibrate for different $K$ using topology-specific bias functions.}\n\\label{alg:correction}\n\\small\n\\begin{algorithmic}[1]\n\\REQUIRE DAG topology $\\mathcal{T}$, gold-label availability $G \\in \\{\\textsc{yes}, \\textsc{no}\\}$\n\\ENSURE Recommended method $M$, risk level $R$\n\\STATE\n\\STATE \\textbf{Step 0: DAG uncertainty} \\COMMENT{If $\\mathcal{T}$ is uncertain, repeat Steps 1--3 under each candidate topology and report the range}\n\\STATE\n\\STATE \\textbf{Step 1: Assess risk level}\n\\IF{$\\mathcal{T} \\in \\{\\text{M-bias}\\}$}\n    \\STATE $R \\gets \\textsc{Low}$ \\COMMENT{$|\\text{bias}| < 0.04$ for all $C$}\n\\ELSIF{$\\mathcal{T} \\in \\{\\text{Conf., Med., Coll., Front-door}\\}$}\n    \\STATE $R \\gets \\textsc{Medium}$ \\COMMENT{bounded bias, no sign reversal}\n\\ELSE\n    \\STATE $R \\gets \\textsc{High}$ \\COMMENT{Exposure, IV: sign reversal 83.4\\% / 52.6\\%}\n\\ENDIF\n\\STATE\n\\STATE \\textbf{Step 2: Select correction method}\n\\IF{$G = \\textsc{yes}$}\n    \\IF{$\\mathcal{T} = \\text{M-bias}$}\n        \\STATE $M \\gets \\textsc{None}$ \\COMMENT{PPI++ RMSE red.\\ $-$88.0\\%; no correction preferred}\n    \\ELSE\n        \\STATE $M \\gets \\text{PPI++}$ \\COMMENT{47.0\\% RMSE red., 96.8\\% coverage}\n    \\ENDIF\n\\ELSE\n    \\STATE \\COMMENT{no gold labels}\n    \\IF{$\\mathcal{T} \\in \\{\\text{Confounding, Mediation}\\}$}\n        \\STATE $M \\gets \\text{DSL}$ \\COMMENT{48.0\\% / 52.9\\% RMSE reduction}\n    \\ELSIF{$\\mathcal{T} = \\text{IV}$}\n        \\STATE $M \\gets \\text{MC-SIMEX}$ \\COMMENT{59.4\\% RMSE reduction}\n    \\ELSIF{$\\mathcal{T} \\in \\{\\text{Collider, M-bias}\\}$}\n        \\STATE $M \\gets \\text{MC-SIMEX}$ \\COMMENT{31.8\\% / 0.1\\% RMSE reduction}\n    \\ELSE\n        \\STATE $M \\gets \\emptyset$; flag: acquire gold labels \\COMMENT{no reliable gold-free method}\n    \\ENDIF\n\\ENDIF\n\\STATE\n\\STATE \\textbf{Step 3: FWL invariance warning}\n\\IF{$\\mathcal{T} \\in \\{\\text{Conf., Med., Coll., M-bias}\\}$}\n    \\STATE Skip Naive plug-in and MLA \\COMMENT{0\\% bias red.\\ on $T$ coeff.\\ (Table~\\ref{tab:correction}: below 2\\%, no method improves)}\n\\ENDIF\n\\RETURN $(M, R)$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\subsection{Proof of FWL Invariance}\n\\label{app:fwl_proof}\n\nFor the four topologies where $A$ enters as a covariate (confounding, mediation, collider, M-bias), the regression is $Y = \\tau T + \\boldsymbol{\\gamma}^\\top \\mathbf{D}^* + \\varepsilon$, where $\\mathbf{D}^*$ is the $N \\times (K{-}1)$ dummy matrix for $A^*$. Any matrix-based correction replaces $\\mathbf{D}^*$ with $\\tilde{\\mathbf{D}} = \\mathbf{D}^* M$ for some invertible $(K{-}1) \\times (K{-}1)$ matrix $M$ (e.g., $M = C^{-1}$ for plug-in, or $M = (C^\\top C)^{-1} C^\\top$ for MLE). By the Frisch--Waugh--Lovell theorem~\\cite{lovell1963}, $\\hat{\\tau}$ depends only on the residual of $T$ projected off $\\operatorname{col}(\\mathbf{D}^*)$. Since $\\operatorname{col}(\\mathbf{D}^* M) = \\operatorname{col}(\\mathbf{D}^*)$ for invertible $M$, the projection is unchanged and $\\hat{\\tau}(\\tilde{\\mathbf{D}}) = \\hat{\\tau}(\\mathbf{D}^*)$ exactly. SIMEX adds noise $\\mathbf{D}^*_{\\text{sim}} = \\mathbf{D}^* + \\lambda \\mathbf{E}$; when $\\mathbf{E}$ is generated from the same column space, the extrapolation to $\\lambda = -1$ converges to a column-space-equivalent transformation, yielding 0\\% bias reduction empirically.\n\n\\paragraph{FWL breakdown under logistic regression.}\n\\label{sec:fwl_logistic}\nThe column-space argument applies only to estimators whose treatment coefficient is a function of $T$ residualized off $\\operatorname{col}(\\mathbf{D}^*)$---a property of linear projection. The logistic MLE solves $\\sum_i (Y_i - \\sigma(\\mathbf{x}_i^\\top\\boldsymbol{\\beta}))\\mathbf{x}_i = \\mathbf{0}$; the implicit weighting by $\\sigma'(\\cdot)$ depends on the actual values of the design columns, not only on their span, so replacing $\\mathbf{D}^*$ by $\\mathbf{D}^* M$ generally changes the fitted $\\hat\\tau$. We verify this on the confounding topology ($K{=}3$, $\\tau{=}0.5$, $N{=}10{,}000\\times 500$ MC reps) under both linear ($Y = \\tau T + \\mathbf{D}\\boldsymbol{\\beta}+\\varepsilon$) and logistic ($Y\\sim\\mathrm{Bern}(\\sigma(\\tau T + \\mathbf{D}\\boldsymbol{\\beta}))$) DGPs, comparing the uncorrected estimator (fit on $\\mathbf{D}^*$) against Naive plug-in (fit on per-sample $(C^{-1}\\mathbf{e}_{A^*})_{1:K}$). Per-rep estimates are paired (same $A^*$, same outcome).\n\n\\begin{table}[h]",
      "numLines": 200,
      "startLine": 750,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "cc10219f-f601-4250-ac1b-92f5e866a0c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 78 · 2026-05-24T06:37:25.861Z_

<details><summary>↩ Tool result · `toolu_01SCeynC1ry1tUAYpjEKFF8o`</summary>

```text
docs/paper/method.tex:31:\label{eq:confounding}
docs/paper/method.tex:39:\label{eq:exposure}
docs/paper/method.tex:58:\label{eq:mediation}
docs/paper/k3_symmetric_proof.tex:19:  q_j(s) &= \textstyle\sum_k C(\delta)_{jk}\,p_k = (1{-}3s)\,p_j + s, \label{eq:k3q} \\
docs/paper/k3_symmetric_proof.tex:21:  = \bar{g} + \frac{(1{-}3s)\,p_j\,h_j}{q_j(s)}, \label{eq:k3mu}
docs/paper/k3_symmetric_proof.tex:30:  \label{eq:k3VB}
docs/paper/k3_symmetric_proof.tex:41:  \label{eq:k3dVB}
docs/paper/appendix_proofs.tex:14:  q_j &= P(A^*{=}j) = \textstyle\sum_k C_{jk}\,p_k, \label{eq:q}\\
docs/paper/appendix_proofs.tex:15:  \mathrm{ct}_j &= \mathbb{E}[T\cdot D_j^*] = \textstyle\sum_k C_{jk}\,\mathbb{E}[T\cdot D_k], \label{eq:ct}\\
docs/paper/appendix_proofs.tex:16:  \mathrm{cy}_j &= \mathbb{E}[Y\cdot D_j^*] = \textstyle\sum_k C_{jk}\,\mathbb{E}[Y\cdot D_k]. \label{eq:cy}
docs/paper/appendix_proofs.tex:28:  \label{eq:fwl}
docs/paper/appendix_proofs.tex:38:  \label{eq:bias_decomp}
docs/paper/appendix_proofs.tex:42:  R(C) &= \mathbb{E}\bigl[\operatorname{Cov}(T,\,f(A)\mid A^*)\bigr], \label{eq:R}\\
docs/paper/appendix_proofs.tex:43:  D(C) &= \mathbb{E}\bigl[\operatorname{Var}(T\mid A^*)\bigr] > 0. \label{eq:D}
docs/paper/appendix_proofs.tex:90:  \label{eq:plim_conf}
docs/paper/appendix_proofs.tex:116:  \label{eq:bias_conf}
docs/paper/appendix_proofs.tex:123:  \label{eq:lotc}
docs/paper/appendix_proofs.tex:132:  \label{eq:bov}
docs/paper/appendix_proofs.tex:145:  \label{eq:convex}
docs/paper/appendix_proofs.tex:181:  \label{eq:bbar}
docs/paper/appendix_proofs.tex:254:\label{eq:dVB}
docs/paper/appendix_proofs.tex:311:  \label{eq:dd_condition}
docs/paper/appendix_proofs.tex:333:  \label{eq:med_bias}
docs/paper/appendix_proofs.tex:440:\label{eq:lambda_def}
docs/paper/appendix_proofs.tex:481:\label{eq:vb_ratio}
docs/paper/appendix_proofs.tex:530:  \label{eq:bias_col}
docs/paper/appendix_proofs.tex:573:  \label{eq:bbar_col}
docs/paper/appendix_proofs.tex:629:  \label{eq:fd_decomp}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6c3f9128-81eb-46e9-bbda-71f1969cdb08",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "f75713d4-9bfd-4b7d-8ad2-028d4bc4cb43",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/method.tex:31:\\label{eq:confounding}\ndocs/paper/method.tex:39:\\label{eq:exposure}\ndocs/paper/method.tex:58:\\label{eq:mediation}\ndocs/paper/k3_symmetric_proof.tex:19:  q_j(s) &= \\textstyle\\sum_k C(\\delta)_{jk}\\,p_k = (1{-}3s)\\,p_j + s, \\label{eq:k3q} \\\\\ndocs/paper/k3_symmetric_proof.tex:21:  = \\bar{g} + \\frac{(1{-}3s)\\,p_j\\,h_j}{q_j(s)}, \\label{eq:k3mu}\ndocs/paper/k3_symmetric_proof.tex:30:  \\label{eq:k3VB}\ndocs/paper/k3_symmetric_proof.tex:41:  \\label{eq:k3dVB}\ndocs/paper/appendix_proofs.tex:14:  q_j &= P(A^*{=}j) = \\textstyle\\sum_k C_{jk}\\,p_k, \\label{eq:q}\\\\\ndocs/paper/appendix_proofs.tex:15:  \\mathrm{ct}_j &= \\mathbb{E}[T\\cdot D_j^*] = \\textstyle\\sum_k C_{jk}\\,\\mathbb{E}[T\\cdot D_k], \\label{eq:ct}\\\\\ndocs/paper/appendix_proofs.tex:16:  \\mathrm{cy}_j &= \\mathbb{E}[Y\\cdot D_j^*] = \\textstyle\\sum_k C_{jk}\\,\\mathbb{E}[Y\\cdot D_k]. \\label{eq:cy}\ndocs/paper/appendix_proofs.tex:28:  \\label{eq:fwl}\ndocs/paper/appendix_proofs.tex:38:  \\label{eq:bias_decomp}\ndocs/paper/appendix_proofs.tex:42:  R(C) &= \\mathbb{E}\\bigl[\\operatorname{Cov}(T,\\,f(A)\\mid A^*)\\bigr], \\label{eq:R}\\\\\ndocs/paper/appendix_proofs.tex:43:  D(C) &= \\mathbb{E}\\bigl[\\operatorname{Var}(T\\mid A^*)\\bigr] > 0. \\label{eq:D}\ndocs/paper/appendix_proofs.tex:90:  \\label{eq:plim_conf}\ndocs/paper/appendix_proofs.tex:116:  \\label{eq:bias_conf}\ndocs/paper/appendix_proofs.tex:123:  \\label{eq:lotc}\ndocs/paper/appendix_proofs.tex:132:  \\label{eq:bov}\ndocs/paper/appendix_proofs.tex:145:  \\label{eq:convex}\ndocs/paper/appendix_proofs.tex:181:  \\label{eq:bbar}\ndocs/paper/appendix_proofs.tex:254:\\label{eq:dVB}\ndocs/paper/appendix_proofs.tex:311:  \\label{eq:dd_condition}\ndocs/paper/appendix_proofs.tex:333:  \\label{eq:med_bias}\ndocs/paper/appendix_proofs.tex:440:\\label{eq:lambda_def}\ndocs/paper/appendix_proofs.tex:481:\\label{eq:vb_ratio}\ndocs/paper/appendix_proofs.tex:530:  \\label{eq:bias_col}\ndocs/paper/appendix_proofs.tex:573:  \\label{eq:bbar_col}\ndocs/paper/appendix_proofs.tex:629:  \\label{eq:fd_decomp}",
    "numLines": 28
  },
  "sourceToolAssistantUUID": "6c3f9128-81eb-46e9-bbda-71f1969cdb08",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 79 · 2026-05-24T06:37:26.613Z_

<details open><summary>🔧 Tool call — Read · `toolu_01R5Mu8sCwjB1rAZJSaBVtZ8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 750,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f75713d4-9bfd-4b7d-8ad2-028d4bc4cb43",
  "isSidechain": false,
  "requestId": "req_011CbLw2FnNhE1EQYa5mz3Bt",
  "type": "assistant",
  "uuid": "cc10219f-f601-4250-ac1b-92f5e866a0c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGBa2ojPZQengvBfyUG2sB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21464,
      "cache_read_input_tokens": 64722,
      "output_tokens": 360,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 360,
          "cache_read_input_tokens": 64722,
          "cache_creation_input_tokens": 21464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21464
          },
          "type": "message"
        }
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
  "leafUuid": "6cf412c7-56b2-4ae9-ba59-cdad0f7062fd",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 81_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 82 · 2026-05-24T06:38:06.073Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me analyze the formulas for duplication.

**Main text equations (method.tex):**
1. `eq:confounding` (method:31) — confounding plim formula
2. `eq:exposure` (method:39) — exposure coefficient formula
3. `eq:mediation` (method:58) — mediation plim formula

**Appendix equations:**
- `eq:q`, `eq:ct`, `eq:cy` — new notation definitions (appendix-only)
- `eq:fwl` — FWL decomposition (appendix-only)
- `eq:bias_decomp` — bias decomposition (appendix-only)


- `eq:R`, `eq:D` — R(C) and D(C) definitions (appendix-only)
- `eq:plim_conf` — confounding plim with more detail than the main text version
- `eq:bias_conf` — bias structure (appendix-only)
- `eq:lotc` — law of total covariance (appendix-only)
- `eq:bov` — omitted variable bias (appendix-only)
- `eq:convex` — convex decomposition (appendix-only)
- `eq:bbar` — worst-case bias bound (appendix-only)
- `eq:dVB` — derivative of V_B (appendix-only)
- `eq:dd_condition` — diagonal dominance (appendix-only)
- `eq:med_bias` — mediation bias decomposition
- `eq:lambda_def` — lambda definition (appendix-only)
- `eq:vb_ratio` — variance ratio (appendix-only)
- `eq:bias_col` — collider bias (appendix-only)
- `eq:bbar_col` — collider bias bound (appendix-only)
- `eq:fd_decomp` — front-door decomposition (appendix-only)

I'm also tracking the K=3 specific equations from the symmetric proof file, which are all relegated to the appendix.

Now I'm checking for any overlapping definitions across sections. The confounding equations in the method section and appendix use different formulations—one in matrix notation and one in scalar form—so they're distinct. For the mediation bias equations, I need to verify whether the direct effect estimator in the methods section duplicates what's in the appendix. I see these are two different parameterizations of the same bias term — the main text uses a lambda weighting approach while the appendix derives it through the Frisch-Waugh-Lovell framework. Let me search through the document more systematically to identify whether the appendix actually restates formulas that already appear in the main text. I'm checking the mediation section more carefully now. The equation at line 332-333 is labeled as eq:med_bias and presents a different formulation than eq:mediation from the main text, so it's not a duplicate. Let me examine the exposure section next.

Looking at the appendix content around lines 672-736, the exposure section walks through a counterexample proof rather than restating eq:exposure. I'm also checking the collider section — the bias formula there is presented in a different form than anything labeled in the main text. So far I'm not finding clear formula duplication between the main text and appendix; instead, the appendix appears to provide proofs and derivations using related but distinct formulations.

Now I need to scan through the remaining appendix sections more systematically — the FWL proof section, case studies, and any content beyond line 950 — to see if there are other duplications I've missed.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6cf412c7-56b2-4ae9-ba59-cdad0f7062fd",
  "isSidechain": false,
  "requestId": "req_011CbLw2wK9gYkfeGvJtbL1v",
  "type": "assistant",
  "uuid": "a78e0e9d-1cf4-4831-9f06-f362668d10ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JJyZDrf1MWR9pQYUiwN2ec",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7428,
      "cache_read_input_tokens": 86186,
      "output_tokens": 2178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7428,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2178,
          "cache_read_input_tokens": 86186,
          "cache_creation_input_tokens": 7428,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7428
          },
          "type": "message"
        }
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

_source line 83 · 2026-05-24T06:38:06.100Z_

Let me read the remaining appendix sections to check for formula duplication.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a78e0e9d-1cf4-4831-9f06-f362668d10ed",
  "isSidechain": false,
  "requestId": "req_011CbLw2wK9gYkfeGvJtbL1v",
  "type": "assistant",
  "uuid": "b744e751-de73-453b-8c6e-5418f6caf5a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JJyZDrf1MWR9pQYUiwN2ec",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7428,
      "cache_read_input_tokens": 86186,
      "output_tokens": 2178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7428,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2178,
          "cache_read_input_tokens": 86186,
          "cache_creation_input_tokens": 7428,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7428
          },
          "type": "message"
        }
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

_source line 84 · 2026-05-24T06:38:07.954Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EUMaDHxhqCTyqgFot6auAj`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 950,
  "limit": 120
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b744e751-de73-453b-8c6e-5418f6caf5a4",
  "isSidechain": false,
  "requestId": "req_011CbLw2wK9gYkfeGvJtbL1v",
  "type": "assistant",
  "uuid": "abb9488d-a2f2-4ef1-8a2b-e9b6685ed9d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JJyZDrf1MWR9pQYUiwN2ec",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7428,
      "cache_read_input_tokens": 86186,
      "output_tokens": 2178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7428,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2178,
          "cache_read_input_tokens": 86186,
          "cache_creation_input_tokens": 7428,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7428
          },
          "type": "message"
        }
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

_source line 85 · 2026-05-24T06:38:08.670Z_

<details><summary>↩ Tool result · `toolu_01PXRgoWRsu7YbcCrCn1iLRs`</summary>

```text
1070	Topology & Linear SF$_\tau$ & Logistic SF$_\tau$ & Linear SF$_\text{any}$ & Logistic SF$_\text{any}$ \\
1071	\midrule
1072	Confounding & 0.000 & 0.000 & 0.573 & 0.559 \\
1073	Mediation & 0.000 & 0.000 & 0.703 & 0.695 \\
1074	Collider & 0.000 & 0.000 & 0.060 & 0.060 \\
1075	Exposure & --- & --- & 0.577 & 0.574 \\
1076	M-bias & 0.000 & 0.000 & 0.095 & 0.099 \\
1077	Front-door & 0.000 & 0.000 & 0.590 & 0.579 \\
1078	IV & 0.086 & 0.074 & 0.086 & 0.560 \\
1079	\bottomrule
1080	\end{tabular}
1081	\end{center}
1082	
1083	Treatment-effect sign-flip rates (SF$_\tau$) are zero for all five guaranteed topologies under both linear and logistic DGPs, and differ by $< 0.02$ for IV. The SF$_\text{any}$ discrepancy for IV reflects estimator dimensionality: the control function includes a residual coefficient prone to sign noise; the core comparison is SF$_\tau$, where both estimators agree. Linear and logistic DGPs produce virtually identical sign-flip patterns across all seven topologies ($|\Delta\,\text{SF}_\tau| < 0.02$). Under logistic DGP, bias is measured in log-odds units; directional conclusions (sign preservation, topology ranking) transfer directly, while magnitudes are not directly comparable to linear plim expressions. For practitioners requiring finite-sample inference under logistic DGP, bias-corrected bootstrap provides a nonparametric alternative that bypasses the linear plim framework.
1084	
1085	\subsection{Bootstrap Uncertainty of ASV}
1086	\label{sec:bootstrap_asv}
1087	
1088	We assess confusion-matrix estimation uncertainty by bootstrapping label pairs from HumAID DeepSeek zero-shot ($K{=}10$, $n{=}1{,}500$): resample with replacement $B{=}1{,}000$ times, re-estimate $C_0$, and recompute magnitude ASV $\delta^*$ at a 10\% bias threshold.
1089	
1090	\begin{center}
1091	\small
1092	\begin{tabular}{lccc}
1093	\toprule
1094	Topology & $\delta^*$ (point) & 95\% CI & Valid / 1000 \\
1095	\midrule
1096	Confounding & --- & --- & 0 \\
1097	Exposure & 0.937 & [0.602, 1.363] & 907 \\
1098	IV & 0.754 & [0.435, 1.290] & 902 \\
1099	\bottomrule
1100	\end{tabular}
1101	\end{center}
1102	
1103	Confounding never reaches the 10\% threshold across all 1{,}000 bootstraps, confirming robustness. For IV, the 95\% CI spans a $3{\times}$ range (0.435 to 1.290); practitioners should bootstrap $C_0$ rather than rely on a point estimate when ASV is near the decision boundary. CI width scales as $O(1/\sqrt{n})$ where $n$ is the gold-label validation set size; at $n{=}1{,}500$, IV CIs are ${\sim}3{\times}$ wider than exposure CIs, reflecting the Wald estimator's denominator instability. A convergence study ($K{=}3$, $B{=}1{,}000$) confirms this scaling: exposure CI width narrows from 0.60 ($n{=}500$) to 0.05 ($n{=}50{,}000$), and IV from 0.52 to 0.04, with the product $\text{width} \times \sqrt{n}$ approximately constant (CV $< 0.20$).
1104	
1105	\begin{figure}[h]
1106	\centering
1107	\includegraphics[width=0.9\columnwidth]{exp_c_bootstrap_figure.pdf}
1108	\caption{Bootstrap distribution of magnitude ASV $\delta^*$ ($B{=}1{,}000$) for HumAID DeepSeek zero-shot ($K{=}10$). Dashed line: point estimate; shaded: 95\% CI.}
1109	\label{fig:bootstrap_asv}
1110	\end{figure}
1111	
1112	\subsection{Cross-$K$ Robustness}
1113	\label{sec:cross_k_robustness}
1114	
1115	All structural patterns persist at $K{=}5,7$ (100{,}000 matrices each): sign-flip guarantees hold for the same five topologies, and IV sign-flip rates remain within 51--53\%.
1116	
1117	\subsection{ASV Diagnostic Results}
1118	\label{sec:asv_diagnostics}
1119	
1120	For HumAID ($K{=}10$, 56 scenarios), 55.4\% are flagged as magnitude-ASV-unsafe---IV, mediation, front-door, and exposure all trigger, while confounding, collider, and M-bias remain below 10\% bias (Figure~\ref{fig:asv_heatmap}). For CivilComments ($K{=}2$), 100\% of scenarios are ASV-unsafe despite $F_1$ ranging from $0.69$ (7B) to $0.82$ (frontier).
1121	
1122	Overlaying all 23 empirical matrices onto the theoretical Dirichlet violation-rate curves (Figure~\ref{fig:dirichlet_overlay}) confirms placement: VAST in the danger zone, HumAID mid-range, CivilComments approaching safe for exposure but still in IV amplification.
1123	
1124	\subsection{ASV Stability Across DGP Parameters}
1125	\label{sec:asv_stability}
1126	
1127	We test whether ASV rankings are stable across different data-generating process (DGP) configurations by varying the treatment-effect vector $\boldsymbol{\beta}$ across three settings: alternating-large ($\boldsymbol{\beta}=[0,\,1.0,\,-0.5]$), same-sign ($\boldsymbol{\beta}=[0,\,0.5,\,0.3]$), and alternating-small ($\boldsymbol{\beta}=[0,\,0.2,\,-0.1]$), with $K{=}3$, $\tau{=}0.5$, and five $C_0$ diagonal values $\in\{0.5,0.6,0.7,0.8,0.9\}$.
1128	
1129	\input{exp_e_asv_stability_table.tex}
1130	
1131	Three patterns emerge (Table~\ref{tab:asv_stability}). First, IV magnitude ASV is identical across all three DGPs ($\delta^*{=}0.203$). This is a mathematical identity, not an empirical finding: the Wald estimator $\hat{\tau}_{\text{IV}} = \text{RF}/\text{FS}$ has $\boldsymbol{\beta}$ in both numerator and denominator, and the ratio depends only on $C$ and the first-stage structure, making ASV invariant to $\boldsymbol{\beta}$ by construction. Second, exposure ASV depends on the coefficient ratio structure: alternating-large ($\beta_2/\beta_1 = -0.5$) and alternating-small ($\beta_2/\beta_1 = -0.5$) share the same ratio and yield identical $\delta^*{=}0.090$, while same-sign ($\beta_2/\beta_1 = 0.6$) gives $\delta^*{=}0.223$---thus the experiment provides two distinct sign-structure conditions, not three. Third, confounding ASV depends on effect magnitudes: only alternating-large triggers the 10\% threshold ($\delta^*{=}0.348$); smaller effects never reach 10\% bias.
1132	
1133	Confounding is consistently the most robust topology (highest ASV or no violation), and M-bias remains immune (not shown). However, the relative fragility of exposure vs.\ IV inverts with coefficient sign structure: under alternating signs, exposure is most fragile ($0.090 < 0.203$); under same-sign effects, IV is most fragile ($0.203 < 0.223$). Practitioners should compute ASV with their specific DGP rather than relying on generic rankings.
1134	
1135	\subsection{Extended Conjecture Verification}
1136	\label{sec:conjecture_verify}
1137	
1138	We test envelope monotonicity (Conjecture~\ref{conj:monotone}) by sampling 10{,}000 random $C_0$ matrices from Dirichlet$(1,\dots,1)$ per topology for $K \in \{3,5,7\}$ (210{,}000 total), sweeping $\delta$ in steps of 0.01, and counting matrices with at least one non-monotonic step exceeding tolerance $10^{-12}$. Bias at each $\delta$ is computed via analytic probability limits using Gauss--Hermite quadrature (100 points), eliminating sampling noise entirely.
1139	
1140	\begin{table}[h]
1141	\centering
1142	\small
1143	\caption{Envelope monotonicity violations per 10{,}000 random $C_0$ matrices ($\delta$ step $= 0.01$). ``Worst mag.''\ is the largest single-step deviation $|B(\delta_{i+1})|-|B(\delta_i)|$ in the non-monotonic direction. $^*$100{,}000 matrices at step $= 0.005$ yield exposure $\varepsilon = 0.075$.}
1144	\label{tab:conjecture_verify}
1145	\begin{tabular}{lccccc}
1146	\toprule
1147	\textbf{Topology} & $K{=}3$ & $K{=}5$ & $K{=}7$ & \textbf{Worst mag.} & \textbf{Direction} \\
1148	\midrule
1149	Confounding & 8467 & 8063 & 7892 & 0.011 & non-dec \\
1150	Mediation   & 8236 & 7905 & 7893 & 0.013 & non-dec \\
1151	Collider    & 8683 & 7669 & 7570 & 0.005 & non-inc \\
1152	Exposure    & 485  & 205  & 77   & 0.056$^*$ & non-dec \\
1153	M-bias      & 9791 & 7783 & 7399 & 0.002 & non-inc \\
1154	IV          & 7433 & 6015 & 5711 & $>10^6$ & non-dec \\
1155	Front-door  & 8429 & 8079 & 7899 & 0.013 & non-dec \\
1156	\bottomrule
1157	\end{tabular}
1158	\end{table}
1159	
1160	Violation counts are high (60--97\% of matrices), but magnitudes are small for non-IV topologies under the default parameterization (Table~\ref{tab:conjecture_verify}); DGP sensitivity analysis (Table~\ref{tab:dgp_sensitivity}) shows $\varepsilon$ scales with effect magnitude $|\beta|$, remaining below 0.02 for $|\beta| \leq 1$ across non-exposure topologies. These results are computed from analytic probability limits with zero sampling noise, confirming the violations are structural properties of multi-class confusion matrices rather than numerical artifacts. IV deviations reflect Wald estimator singularities when the first-stage coefficient passes near zero---this is a property of the Wald estimator, not of the ASV parameterization. Adversarial search (500 restarts per configuration, $K \in \{3,5\}$) finds genuine counterexamples for all topologies except IV $K{=}3$, confirming that strict monotonicity does not hold universally. The bias envelope is $\varepsilon$-approximately monotonic with $\varepsilon < 0.03$ for collider and M-bias across all tested $\tau$; confounding, mediation, and front-door achieve $\varepsilon < 0.06$ at default DGP parameters (see DGP sensitivity below); exposure satisfies $\varepsilon_{p99} < 0.008$ but extreme-tail matrices ($<$0.02\% of draws) reach $\varepsilon \approx 0.15$. Empirically, $\varepsilon$ scales as $O(1/K^\alpha)$ with $\alpha \in [0.6, 1.5]$ (topology-dependent): for confounding, mediation, and front-door, $\alpha \approx 1.4$; for exposure, $\alpha \approx 1.0$; for collider and M-bias, $\alpha \approx 0.7$. A universal empirical upper bound is $\varepsilon \leq 0.137/\sqrt{K}$, verified across all tested configurations ($K \in \{3,5,7\}$). This scaling supports the practical validity of ASV as a sensitivity tool at any meaningful bias threshold.
1161	
1162	\paragraph{DGP parameter sensitivity.}
1163	We repeat the verification across $\tau \in \{0.1, 0.5, 1.0, 2.0, 5.0\}$, varying the direct $T{\to}Y$ coefficient for confounding ($\beta_T{=}\tau$), mediation, collider, and M-bias (DGP $\tau$), and rescaling the $A{\to}Y$ coefficient vector to $\boldsymbol{\beta}\cdot\tau$ for exposure and front-door. With 10{,}000 random $C_0$ per $(K,\tau)$ setting (Table~\ref{tab:conjecture_tau_sens}), $\varepsilon$ remains small ($< 0.03$) for $\tau \geq 0.5$ for confounding, mediation, collider, and M-bias, but grows at $\tau{=}0.1$: mediation produces 1{,}950 / 30{,}000 violations across $K \in \{3,5,7\}$ (worst $\varepsilon{=}0.130$ at $K{=}3$) and confounding 200 / 30{,}000 (worst $\varepsilon{=}0.118$ at $K{=}3$). The mechanism is dimensional: additive terms not scaling with $\tau$ (e.g.\ the $\boldsymbol{\beta}$-contribution to $\mathbb{E}[Y D_k]$ in mediation and confounding) contribute a $\tau$-independent offset to the bias numerator, so the ratio $|B|/|\tau|$ inflates as $\tau \to 0$. A single mediation violation at $\tau{=}2.0$ ($\varepsilon{=}0.112$, 1/30{,}000 matrices) arises from a specific confusion matrix structure where off-diagonal entries induce partial cancellation along the mediation pathway; this isolated case does not affect the $p_{99}$ bound ($\varepsilon_{p99}{=}0.005$). Collider and M-bias remain robust at all $\tau$ ($\varepsilon{<}0.022$ and $\varepsilon{<}0.015$ respectively). Exposure shows scattered tail outliers but $\overline{\varepsilon} \approx 3\!\times\!10^{-4}$ at every $\tau$, consistent with linear scaling: when $\boldsymbol{\beta}$ rescales by $\tau$, both bias and $\tau_{\text{true}}$ scale by the same factor and $\varepsilon$ is theoretically invariant. Front-door inverts the pattern ($\varepsilon$ \emph{grows} with $\tau$, reaching $0.139$ at $\tau{=}5$, $K{=}3$, with 664 violations) because $\tau_{\text{true}} = \operatorname{plim}(\hat{\tau}_T \mid C{=}I)$ is pinned at $0.5$ by the $U$-confounding path while bias magnitudes scale with $\boldsymbol{\beta}$---this is an artefact of how $\tau_{\text{true}}$ is normalised, not a genuine failure of envelope monotonicity. In practice, ASV's $\delta^*$ thresholds (typically $\geq 0.1$ in our deployment) are well above the region where these $\varepsilon$-violations occur, so the small-$\tau$ degradation does not affect ASV's operational reliability; we flag it as a caveat for applications targeting $|\tau| \lesssim 0.1$ in standardised units.
1164	
1165	\begin{table}[h]
1166	\centering
1167	\small
1168	\caption{$\varepsilon \equiv \max_\delta(|B(\delta{+}\Delta)|{-}|B(\delta)|)/|\tau_{\text{true}}|$ in the non-monotonic direction (max over $K \in \{3,5,7\}$; 10{,}000 random $C_0$ per cell). Bold marks $\varepsilon > 0.02$ (non-exposure) or $\varepsilon > 0.08$ (exposure). Counts in parentheses are violations / 30{,}000. Tables~\ref{tab:conjecture_verify} and~\ref{tab:conjecture_tau_sens} use independent random seeds; for topologies with low violation rates (exposure $<$0.02\%), the worst-case $\varepsilon$ is sample-sensitive.}
1169	\label{tab:conjecture_tau_sens}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ee00c776-6cbb-4a4a-bd59-f7870feb18bb",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "e7b0a4ec-3fce-4773-9935-ce1f25efe3be",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "Topology & Linear SF$_\\tau$ & Logistic SF$_\\tau$ & Linear SF$_\\text{any}$ & Logistic SF$_\\text{any}$ \\\\\n\\midrule\nConfounding & 0.000 & 0.000 & 0.573 & 0.559 \\\\\nMediation & 0.000 & 0.000 & 0.703 & 0.695 \\\\\nCollider & 0.000 & 0.000 & 0.060 & 0.060 \\\\\nExposure & --- & --- & 0.577 & 0.574 \\\\\nM-bias & 0.000 & 0.000 & 0.095 & 0.099 \\\\\nFront-door & 0.000 & 0.000 & 0.590 & 0.579 \\\\\nIV & 0.086 & 0.074 & 0.086 & 0.560 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{center}\n\nTreatment-effect sign-flip rates (SF$_\\tau$) are zero for all five guaranteed topologies under both linear and logistic DGPs, and differ by $< 0.02$ for IV. The SF$_\\text{any}$ discrepancy for IV reflects estimator dimensionality: the control function includes a residual coefficient prone to sign noise; the core comparison is SF$_\\tau$, where both estimators agree. Linear and logistic DGPs produce virtually identical sign-flip patterns across all seven topologies ($|\\Delta\\,\\text{SF}_\\tau| < 0.02$). Under logistic DGP, bias is measured in log-odds units; directional conclusions (sign preservation, topology ranking) transfer directly, while magnitudes are not directly comparable to linear plim expressions. For practitioners requiring finite-sample inference under logistic DGP, bias-corrected bootstrap provides a nonparametric alternative that bypasses the linear plim framework.\n\n\\subsection{Bootstrap Uncertainty of ASV}\n\\label{sec:bootstrap_asv}\n\nWe assess confusion-matrix estimation uncertainty by bootstrapping label pairs from HumAID DeepSeek zero-shot ($K{=}10$, $n{=}1{,}500$): resample with replacement $B{=}1{,}000$ times, re-estimate $C_0$, and recompute magnitude ASV $\\delta^*$ at a 10\\% bias threshold.\n\n\\begin{center}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nTopology & $\\delta^*$ (point) & 95\\% CI & Valid / 1000 \\\\\n\\midrule\nConfounding & --- & --- & 0 \\\\\nExposure & 0.937 & [0.602, 1.363] & 907 \\\\\nIV & 0.754 & [0.435, 1.290] & 902 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{center}\n\nConfounding never reaches the 10\\% threshold across all 1{,}000 bootstraps, confirming robustness. For IV, the 95\\% CI spans a $3{\\times}$ range (0.435 to 1.290); practitioners should bootstrap $C_0$ rather than rely on a point estimate when ASV is near the decision boundary. CI width scales as $O(1/\\sqrt{n})$ where $n$ is the gold-label validation set size; at $n{=}1{,}500$, IV CIs are ${\\sim}3{\\times}$ wider than exposure CIs, reflecting the Wald estimator's denominator instability. A convergence study ($K{=}3$, $B{=}1{,}000$) confirms this scaling: exposure CI width narrows from 0.60 ($n{=}500$) to 0.05 ($n{=}50{,}000$), and IV from 0.52 to 0.04, with the product $\\text{width} \\times \\sqrt{n}$ approximately constant (CV $< 0.20$).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.9\\columnwidth]{exp_c_bootstrap_figure.pdf}\n\\caption{Bootstrap distribution of magnitude ASV $\\delta^*$ ($B{=}1{,}000$) for HumAID DeepSeek zero-shot ($K{=}10$). Dashed line: point estimate; shaded: 95\\% CI.}\n\\label{fig:bootstrap_asv}\n\\end{figure}\n\n\\subsection{Cross-$K$ Robustness}\n\\label{sec:cross_k_robustness}\n\nAll structural patterns persist at $K{=}5,7$ (100{,}000 matrices each): sign-flip guarantees hold for the same five topologies, and IV sign-flip rates remain within 51--53\\%.\n\n\\subsection{ASV Diagnostic Results}\n\\label{sec:asv_diagnostics}\n\nFor HumAID ($K{=}10$, 56 scenarios), 55.4\\% are flagged as magnitude-ASV-unsafe---IV, mediation, front-door, and exposure all trigger, while confounding, collider, and M-bias remain below 10\\% bias (Figure~\\ref{fig:asv_heatmap}). For CivilComments ($K{=}2$), 100\\% of scenarios are ASV-unsafe despite $F_1$ ranging from $0.69$ (7B) to $0.82$ (frontier).\n\nOverlaying all 23 empirical matrices onto the theoretical Dirichlet violation-rate curves (Figure~\\ref{fig:dirichlet_overlay}) confirms placement: VAST in the danger zone, HumAID mid-range, CivilComments approaching safe for exposure but still in IV amplification.\n\n\\subsection{ASV Stability Across DGP Parameters}\n\\label{sec:asv_stability}\n\nWe test whether ASV rankings are stable across different data-generating process (DGP) configurations by varying the treatment-effect vector $\\boldsymbol{\\beta}$ across three settings: alternating-large ($\\boldsymbol{\\beta}=[0,\\,1.0,\\,-0.5]$), same-sign ($\\boldsymbol{\\beta}=[0,\\,0.5,\\,0.3]$), and alternating-small ($\\boldsymbol{\\beta}=[0,\\,0.2,\\,-0.1]$), with $K{=}3$, $\\tau{=}0.5$, and five $C_0$ diagonal values $\\in\\{0.5,0.6,0.7,0.8,0.9\\}$.\n\n\\input{exp_e_asv_stability_table.tex}\n\nThree patterns emerge (Table~\\ref{tab:asv_stability}). First, IV magnitude ASV is identical across all three DGPs ($\\delta^*{=}0.203$). This is a mathematical identity, not an empirical finding: the Wald estimator $\\hat{\\tau}_{\\text{IV}} = \\text{RF}/\\text{FS}$ has $\\boldsymbol{\\beta}$ in both numerator and denominator, and the ratio depends only on $C$ and the first-stage structure, making ASV invariant to $\\boldsymbol{\\beta}$ by construction. Second, exposure ASV depends on the coefficient ratio structure: alternating-large ($\\beta_2/\\beta_1 = -0.5$) and alternating-small ($\\beta_2/\\beta_1 = -0.5$) share the same ratio and yield identical $\\delta^*{=}0.090$, while same-sign ($\\beta_2/\\beta_1 = 0.6$) gives $\\delta^*{=}0.223$---thus the experiment provides two distinct sign-structure conditions, not three. Third, confounding ASV depends on effect magnitudes: only alternating-large triggers the 10\\% threshold ($\\delta^*{=}0.348$); smaller effects never reach 10\\% bias.\n\nConfounding is consistently the most robust topology (highest ASV or no violation), and M-bias remains immune (not shown). However, the relative fragility of exposure vs.\\ IV inverts with coefficient sign structure: under alternating signs, exposure is most fragile ($0.090 < 0.203$); under same-sign effects, IV is most fragile ($0.203 < 0.223$). Practitioners should compute ASV with their specific DGP rather than relying on generic rankings.\n\n\\subsection{Extended Conjecture Verification}\n\\label{sec:conjecture_verify}\n\nWe test envelope monotonicity (Conjecture~\\ref{conj:monotone}) by sampling 10{,}000 random $C_0$ matrices from Dirichlet$(1,\\dots,1)$ per topology for $K \\in \\{3,5,7\\}$ (210{,}000 total), sweeping $\\delta$ in steps of 0.01, and counting matrices with at least one non-monotonic step exceeding tolerance $10^{-12}$. Bias at each $\\delta$ is computed via analytic probability limits using Gauss--Hermite quadrature (100 points), eliminating sampling noise entirely.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Envelope monotonicity violations per 10{,}000 random $C_0$ matrices ($\\delta$ step $= 0.01$). ``Worst mag.''\\ is the largest single-step deviation $|B(\\delta_{i+1})|-|B(\\delta_i)|$ in the non-monotonic direction. $^*$100{,}000 matrices at step $= 0.005$ yield exposure $\\varepsilon = 0.075$.}\n\\label{tab:conjecture_verify}\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Topology} & $K{=}3$ & $K{=}5$ & $K{=}7$ & \\textbf{Worst mag.} & \\textbf{Direction} \\\\\n\\midrule\nConfounding & 8467 & 8063 & 7892 & 0.011 & non-dec \\\\\nMediation   & 8236 & 7905 & 7893 & 0.013 & non-dec \\\\\nCollider    & 8683 & 7669 & 7570 & 0.005 & non-inc \\\\\nExposure    & 485  & 205  & 77   & 0.056$^*$ & non-dec \\\\\nM-bias      & 9791 & 7783 & 7399 & 0.002 & non-inc \\\\\nIV          & 7433 & 6015 & 5711 & $>10^6$ & non-dec \\\\\nFront-door  & 8429 & 8079 & 7899 & 0.013 & non-dec \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nViolation counts are high (60--97\\% of matrices), but magnitudes are small for non-IV topologies under the default parameterization (Table~\\ref{tab:conjecture_verify}); DGP sensitivity analysis (Table~\\ref{tab:dgp_sensitivity}) shows $\\varepsilon$ scales with effect magnitude $|\\beta|$, remaining below 0.02 for $|\\beta| \\leq 1$ across non-exposure topologies. These results are computed from analytic probability limits with zero sampling noise, confirming the violations are structural properties of multi-class confusion matrices rather than numerical artifacts. IV deviations reflect Wald estimator singularities when the first-stage coefficient passes near zero---this is a property of the Wald estimator, not of the ASV parameterization. Adversarial search (500 restarts per configuration, $K \\in \\{3,5\\}$) finds genuine counterexamples for all topologies except IV $K{=}3$, confirming that strict monotonicity does not hold universally. The bias envelope is $\\varepsilon$-approximately monotonic with $\\varepsilon < 0.03$ for collider and M-bias across all tested $\\tau$; confounding, mediation, and front-door achieve $\\varepsilon < 0.06$ at default DGP parameters (see DGP sensitivity below); exposure satisfies $\\varepsilon_{p99} < 0.008$ but extreme-tail matrices ($<$0.02\\% of draws) reach $\\varepsilon \\approx 0.15$. Empirically, $\\varepsilon$ scales as $O(1/K^\\alpha)$ with $\\alpha \\in [0.6, 1.5]$ (topology-dependent): for confounding, mediation, and front-door, $\\alpha \\approx 1.4$; for exposure, $\\alpha \\approx 1.0$; for collider and M-bias, $\\alpha \\approx 0.7$. A universal empirical upper bound is $\\varepsilon \\leq 0.137/\\sqrt{K}$, verified across all tested configurations ($K \\in \\{3,5,7\\}$). This scaling supports the practical validity of ASV as a sensitivity tool at any meaningful bias threshold.\n\n\\paragraph{DGP parameter sensitivity.}\nWe repeat the verification across $\\tau \\in \\{0.1, 0.5, 1.0, 2.0, 5.0\\}$, varying the direct $T{\\to}Y$ coefficient for confounding ($\\beta_T{=}\\tau$), mediation, collider, and M-bias (DGP $\\tau$), and rescaling the $A{\\to}Y$ coefficient vector to $\\boldsymbol{\\beta}\\cdot\\tau$ for exposure and front-door. With 10{,}000 random $C_0$ per $(K,\\tau)$ setting (Table~\\ref{tab:conjecture_tau_sens}), $\\varepsilon$ remains small ($< 0.03$) for $\\tau \\geq 0.5$ for confounding, mediation, collider, and M-bias, but grows at $\\tau{=}0.1$: mediation produces 1{,}950 / 30{,}000 violations across $K \\in \\{3,5,7\\}$ (worst $\\varepsilon{=}0.130$ at $K{=}3$) and confounding 200 / 30{,}000 (worst $\\varepsilon{=}0.118$ at $K{=}3$). The mechanism is dimensional: additive terms not scaling with $\\tau$ (e.g.\\ the $\\boldsymbol{\\beta}$-contribution to $\\mathbb{E}[Y D_k]$ in mediation and confounding) contribute a $\\tau$-independent offset to the bias numerator, so the ratio $|B|/|\\tau|$ inflates as $\\tau \\to 0$. A single mediation violation at $\\tau{=}2.0$ ($\\varepsilon{=}0.112$, 1/30{,}000 matrices) arises from a specific confusion matrix structure where off-diagonal entries induce partial cancellation along the mediation pathway; this isolated case does not affect the $p_{99}$ bound ($\\varepsilon_{p99}{=}0.005$). Collider and M-bias remain robust at all $\\tau$ ($\\varepsilon{<}0.022$ and $\\varepsilon{<}0.015$ respectively). Exposure shows scattered tail outliers but $\\overline{\\varepsilon} \\approx 3\\!\\times\\!10^{-4}$ at every $\\tau$, consistent with linear scaling: when $\\boldsymbol{\\beta}$ rescales by $\\tau$, both bias and $\\tau_{\\text{true}}$ scale by the same factor and $\\varepsilon$ is theoretically invariant. Front-door inverts the pattern ($\\varepsilon$ \\emph{grows} with $\\tau$, reaching $0.139$ at $\\tau{=}5$, $K{=}3$, with 664 violations) because $\\tau_{\\text{true}} = \\operatorname{plim}(\\hat{\\tau}_T \\mid C{=}I)$ is pinned at $0.5$ by the $U$-confounding path while bias magnitudes scale with $\\boldsymbol{\\beta}$---this is an artefact of how $\\tau_{\\text{true}}$ is normalised, not a genuine failure of envelope monotonicity. In practice, ASV's $\\delta^*$ thresholds (typically $\\geq 0.1$ in our deployment) are well above the region where these $\\varepsilon$-violations occur, so the small-$\\tau$ degradation does not affect ASV's operational reliability; we flag it as a caveat for applications targeting $|\\tau| \\lesssim 0.1$ in standardised units.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{$\\varepsilon \\equiv \\max_\\delta(|B(\\delta{+}\\Delta)|{-}|B(\\delta)|)/|\\tau_{\\text{true}}|$ in the non-monotonic direction (max over $K \\in \\{3,5,7\\}$; 10{,}000 random $C_0$ per cell). Bold marks $\\varepsilon > 0.02$ (non-exposure) or $\\varepsilon > 0.08$ (exposure). Counts in parentheses are violations / 30{,}000. Tables~\\ref{tab:conjecture_verify} and~\\ref{tab:conjecture_tau_sens} use independent random seeds; for topologies with low violation rates (exposure $<$0.02\\%), the worst-case $\\varepsilon$ is sample-sensitive.}\n\\label{tab:conjecture_tau_sens}",
      "numLines": 100,
      "startLine": 1070,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "ee00c776-6cbb-4a4a-bd59-f7870feb18bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 86 · 2026-05-24T06:38:07.969Z_

<details><summary>↩ Tool result · `toolu_01EUMaDHxhqCTyqgFot6auAj`</summary>

```text
950	\centering
951	\small
952	\caption{FWL invariance under OLS vs. breakdown under logistic regression. $|\Delta|_{\max}=\max_m|\hat\tau_{\mathrm{corr}}^{(m)}-\hat\tau_{\mathrm{un}}^{(m)}|$ over 500 MC reps; bias reduction = $1-|\hat\tau_{\mathrm{corr}}-\tau_*|/|\hat\tau_{\mathrm{un}}-\tau_*|$. Confounding DAG, $K{=}3$, $N{=}10{,}000$.}
953	\label{tab:fwl_logistic}
954	\begin{tabular}{lcccc}
955	\toprule
956	 & \multicolumn{2}{c}{\textbf{OLS}} & \multicolumn{2}{c}{\textbf{Logistic}} \\
957	\cmidrule(lr){2-3}\cmidrule(lr){4-5}
958	CM (VAST K=3) & $|\Delta|_{\max}$ & bias red. & $|\Delta|_{\max}$ & bias red. \\
959	\midrule
960	deepseek\_zero-shot     & $2.3\!\times\!10^{-15}$ & $+0.00\%$ & $8.1\!\times\!10^{-4}$ & $-0.09\%$ \\
961	llama4\_few-shot-3      & $5.2\!\times\!10^{-15}$ & $+0.00\%$ & $6.8\!\times\!10^{-4}$ & $-0.07\%$ \\
962	llama4\_few-shot-5      & $4.3\!\times\!10^{-15}$ & $+0.00\%$ & $6.8\!\times\!10^{-4}$ & $-0.06\%$ \\
963	llama4\_zero-shot       & $1.6\!\times\!10^{-15}$ & $+0.00\%$ & $5.9\!\times\!10^{-4}$ & $-0.05\%$ \\
964	qwen2.5-7b\_few-shot-3  & $7.2\!\times\!10^{-15}$ & $-0.00\%$ & $6.8\!\times\!10^{-4}$ & $-0.01\%$ \\
965	qwen2.5-7b\_few-shot-5  & $8.2\!\times\!10^{-15}$ & $+0.00\%$ & $5.6\!\times\!10^{-4}$ & $+0.05\%$ \\
966	\midrule
967	\textbf{Mean}           & ---                     & $\mathbf{0.0\%}$ & ---            & $\mathbf{-0.04\%}$ \\
968	\bottomrule
969	\end{tabular}
970	\end{table}
971	
972	Two findings: (i) Under OLS, $\hat\tau_{\mathrm{corr}}^{(m)}=\hat\tau_{\mathrm{un}}^{(m)}$ to machine precision in every replication, confirming Proposition~\ref{app:fwl_proof} as an exact algebraic identity. (ii) Under logistic regression, per-replication estimates differ by $|\Delta|_{\max}\!\sim\!10^{-3}$---thirteen orders of magnitude larger than the OLS gap---so the invariance fails formally. However, the directional effect on bias is negligible: mean bias reduction is $-0.04\%$ across the six confusion matrices (range $[-0.09\%, +0.05\%]$, not even consistent in sign). Matrix-based corrections remain practically useless under logistic regression---not by an exact invariance, but because the deviation is too small to systematically offset the misclassification-induced bias (which itself is $\sim\!0.10$ in absolute units, two orders of magnitude larger than $|\Delta|$). The routing rule of Algorithm~\ref{alg:correction} (skip Naive/MLA for these four topologies) is therefore conservative-but-correct under logistic regression as well. Script: \texttt{artifacts/exp\_fwl\_logistic\_breakdown.py}; results: \texttt{exp\_fwl\_logistic\_results.json}.
973	
974	\subsection{Applied Illustration: ClinicalBERT Case Study}
975	\label{app:case_study}
976	
977	To demonstrate the framework's end-to-end utility, we apply it retrospectively to \citet{lee_wood_doughty2024}, who use ClinicalBERT to classify patient smoking status ($K{=}4$: never, past, current, unknown) from clinical notes and control for this predicted confounder when estimating the causal effect of echocardiography on mortality in 4{,}735 MIMIC-III sepsis patients.
978	Our taxonomy identifies this as a \emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.
979	Three conclusions follow directly.
980	First, the zero sign-flip guarantee for confounding (Table~\ref{tab:taxonomy}) ensures that the estimated protective effect (OR~$= 0.89$) cannot reverse direction due to annotation error---a reassurance unavailable without topology-specific analysis.
981	Second, the FWL invariance result implies that any correction reducing to $C^{-1}$ applied to the dummy-coded confounder achieves exactly 0\% bias reduction for the treatment coefficient; naive plug-in is provably futile here.
982	Third, our correction guidance ranks PPI++ (83.2\% RMSE reduction for confounding) above MC-SIMEX (35.1\%) when gold labels are available---a concrete recommendation the original study lacked.
983	This example illustrates the intended workflow: DAG identification $\to$ topology-specific guarantees $\to$ correction method selection.
984	
985	\subsection{IV Wald Estimator: Diagonal-Dominance Subspaces}
986	\label{sec:iv_dirichlet_subspace}
987	
988	Section~\ref{sec:taxonomy_results} reports a 52.6\% Wald sign-flip rate
989	over the full Dirichlet$(1,1,1)$ prior. Because realistic LLM confusion
990	matrices are diagonal-dominant, we replicate the exposure-DAG stratification
991	for the IV topology, restricting the sample
992	space to $\{C : \min_k C_{kk} \geq d\}$ for $d \in \{0, 0.5, 0.7, 0.9\}$
993	(100{,}000 random matrices per threshold).
994	
995	\begin{table}[h]
996	\centering
997	\caption{IV Wald estimator bias by minimum-diagonal subspace ($K{=}3$, $\tau_{\text{true}}{=}1.41$).
998	Rates over 100{,}000 Dirichlet-truncated random $C$ per threshold.}
999	\label{tab:iv_dirichlet_subspace}
1000	\small
1001	\begin{tabular}{lcccc}
1002	\toprule
1003	\textbf{Subspace} & \textbf{Violation} & \textbf{Sign Flip} & \textbf{Amplif.} & \textbf{Worst} \\
1004	\midrule
1005	Full           & 100.0\% & 51.7\% & 48.3\% & $10^{5}\!\times$ \\
1006	$d \geq 0.5$   & 100.0\% & 0.0\%  & 100.0\% & $28.6\times$ \\
1007	$d \geq 0.7$   & 100.0\% & 0.0\%  & 100.0\% & $2.4\times$ \\
1008	$d \geq 0.9$   & 100.0\% & 0.0\%  & 100.0\% & $1.2\times$ \\
1009	\bottomrule
1010	\end{tabular}
1011	\end{table}
1012	
1013	The contrast with exposure is instructive: at $d{\geq}0.7$, exposure violation drops to 13.7\% (sign reversal 2.1\%, amplification 11.7\%), while IV maintains 100\% violation with pure amplification. IV sign reversal is entirely driven by pathological (near-random) confusion matrices where the Wald denominator crosses zero; diagonal dominance reduces this crossing to near-zero under empirical accuracy conditions but cannot prevent amplification. Even at $d{\geq}0.9$, the Wald estimator inflates $|\tau|$ by up to $1.24\times$ with probability~1.
1014	
1015	\subsection{Non-Differential Misclassification Verification}
1016	\label{sec:nondiff_verify}
1017	
1018	The non-differential assumption $P(A^*{=}j \mid A{=}k, Y, \mathbf{Z}) = P(A^*{=}j \mid A{=}k)$ holds \emph{by design} in standard LLM annotation pipelines: the model receives only source text as input and classifies without observing the outcome $Y$ or covariates $\mathbf{Z}$. The annotation API call is structurally independent of downstream variables, satisfying the conditional independence requirement.
1019	
1020	To provide empirical support beyond the design argument, we examine topic-stratified confusion matrices using the VAST dataset ($K{=}3$, stance detection), where the \texttt{topic} field (e.g., ``gun control,'' ``college'') serves as a proxy for latent factors correlated with $Y$. Across 10 model configurations (3 LLMs $\times$ 2--4 prompt types) and 19 qualifying topics (minimum 10 samples per topic), we compute per-topic confusion matrices $C_{\text{topic}}(t) = P(A^*{=}j \mid A{=}k, \text{topic}{=}t)$ and compare against the overall $C = P(A^*{=}j \mid A{=}k)$.
1021	
1022	Per-topic sample sizes range from 10 to 42, making individual topic CMs inherently noisy. A bootstrap permutation test ($B{=}10{,}000$) under the non-differential null shows that the expected grand maximum deviation $\max_{t,j,k} |C_{\text{topic}}(j,k) - C(j,k)|$ at the 95th percentile ranges from 0.90 to 0.98 across model configurations---driven by the smallest topics. For the 5 largest topics ($n \geq 28$), expected per-topic max deviation at the 95th percentile is 0.38--0.49, consistent with finite-sample variation rather than systematic topic-dependence. The observed per-topic variation is fully consistent with the non-differential null.
1023	
1024	This proxy-based test is necessarily limited: topic is not the actual outcome $Y$, and small per-topic samples reduce statistical power. The design argument (LLM input excludes $Y$) remains the primary justification; the stress test in Section~\ref{sec:nondiff_stress} below quantifies bias degradation under hypothetical violations.
1025	
1026	\subsection{Non-Differential Assumption Stress Test}
1027	\label{sec:nondiff_stress}
1028	
1029	Our main analysis assumes non-differential misclassification: the confusion matrix $C$ does not depend on the outcome $Y$. To assess sensitivity to violations of this assumption, we conduct a stress test on the exposure topology ($K{=}3$, $\min_k C_{kk} \geq 0.7$, 10{,}000 random matrices per $\varepsilon$). For each base matrix $C_0$, observations with $Y > \text{median}(Y)$ are misclassified using a perturbed matrix $\tilde{C} = \text{renormalize}(C_0 + \varepsilon \cdot \Delta)$ where $\Delta_{jk} \sim \text{Uniform}(-1,1)$ for $j \neq k$, while observations with $Y \leq \text{median}(Y)$ retain $C_0$.
1030	
1031	\begin{table}[h]
1032	\centering
1033	\small
1034	\caption{Effect of differential misclassification on bias violation rates (exposure DAG, $K{=}3$, $\min_k C_{kk} \geq 0.7$, $N{=}50{,}000$ MC samples per trial).}
1035	\label{tab:nondiff_stress}
1036	\begin{tabular}{cccc}
1037	\toprule
1038	$\varepsilon$ & Sign-Flip (\%) & Amplification (\%) & Any Violation (\%) \\
1039	\midrule
1040	0.00 & 2.0 & 11.5 & 13.3 \\
1041	0.01 & 2.4 & 12.4 & 14.7 \\
1042	0.05 & 2.8 & 13.0 & 15.7 \\
1043	0.10 & 4.5 & 16.7 & 20.9 \\
1044	0.20 & 9.7 & 23.7 & 32.6 \\
1045	0.30 & 15.5 & 28.7 & 42.8 \\
1046	0.50 & 22.9 & 34.9 & 54.6 \\
1047	\bottomrule
1048	\end{tabular}
1049	\end{table}
1050	
1051	The $\varepsilon{=}0$ baseline (13.3\% violation) closely matches the analytical result (13.7\%) from Section~\ref{sec:taxonomy_results}. Small departures ($\varepsilon \leq 0.05$) change rates by fewer than 3 percentage points. At $\varepsilon{=}0.10$, the violation rate increases by 7.6~pp; at $\varepsilon{=}0.50$, it rises to 54.6\% (+41.2~pp), indicating substantial sensitivity to large differential error. Our main conclusions hold under mild violations but should be interpreted cautiously when outcome-conditional annotation is suspected.
1052	
1053	\paragraph{Extended stress test.}
1054	An extended stress test across 96 configurations (4 topologies $\times$ 2 $K$ $\times$ 3 CM qualities $\times$ 4 $\varepsilon$, 100 MC replications each; Table~\ref{tab:stress-test}) confirms these patterns broadly: at $\varepsilon{=}0$, sign-flip rates are zero for all configurations; at $\varepsilon{=}0.10$, the maximum sign-flip rate is 7\% (IV, low-quality $C_{kk}{=}0.4$, $K{=}3$). At $K{=}10$, sign-flip rates remain zero for all topologies and $\varepsilon$ values, suggesting that higher $K$ provides additional robustness to differential misclassification.
1055	
1056	\input{exp_a_stress_test_table.tex}
1057	
1058	\paragraph{Structured violation models.}
1059	Beyond uniform perturbations, we compare two structured violation models across all seven topologies ($K{=}3$, 1{,}000 matrices per $\varepsilon$, $\min_k C_{kk}{\geq}0.7$): (1)~\emph{outcome-conditional}, where $\tilde{C}$ applies to $Y{>}\text{median}(Y)$ while $C_0$ applies below; (2)~\emph{label-specific}, where off-diagonal perturbation magnitude scales with $|\text{corr}(A{=}k, Y)|$, modeling accuracy degradation on $Y$-predictive categories. For exposure at $\varepsilon{=}0.20$, label-specific violations are substantially milder than uniform (sign-flip 0.1\% vs.\ 10.1\%), while outcome-conditional violations are more severe (sign-flip 13.9\%, mean relative bias 0.50 vs.\ 0.40). All five sign-preserving topologies maintain 0\% sign-flip under both structured models at all $\varepsilon$ tested; IV likewise shows 0\% sign-flip (its vulnerability requires pathological diagonal structure, not differential error). These results indicate that the uniform perturbation model is neither uniformly conservative nor uniformly liberal: practitioners should assess which violation pattern is most plausible for their annotation pipeline.
1060	
1061	\subsection{Robustness to Nonlinear DGP}
1062	\label{sec:logistic_dgp}
1063	
1064	We replace the linear structural equations with $Y \sim \text{Bernoulli}(\sigma(\mathbf{x}^\top\boldsymbol{\beta}))$ and estimate via logistic regression (control function for IV) for all seven topologies, using $K{=}3$, six real VAST confusion matrices, 500 MC replications, and $N{=}10{,}000$. Mean sign-flip rates across the six CMs:
1065	
1066	\begin{center}
1067	\small
1068	\begin{tabular}{lcccc}
1069	\toprule
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "abb9488d-a2f2-4ef1-8a2b-e9b6685ed9d1",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "90c4f7ae-3c53-480e-bc50-310fb6c8e5b1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\centering\n\\small\n\\caption{FWL invariance under OLS vs. breakdown under logistic regression. $|\\Delta|_{\\max}=\\max_m|\\hat\\tau_{\\mathrm{corr}}^{(m)}-\\hat\\tau_{\\mathrm{un}}^{(m)}|$ over 500 MC reps; bias reduction = $1-|\\hat\\tau_{\\mathrm{corr}}-\\tau_*|/|\\hat\\tau_{\\mathrm{un}}-\\tau_*|$. Confounding DAG, $K{=}3$, $N{=}10{,}000$.}\n\\label{tab:fwl_logistic}\n\\begin{tabular}{lcccc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{OLS}} & \\multicolumn{2}{c}{\\textbf{Logistic}} \\\\\n\\cmidrule(lr){2-3}\\cmidrule(lr){4-5}\nCM (VAST K=3) & $|\\Delta|_{\\max}$ & bias red. & $|\\Delta|_{\\max}$ & bias red. \\\\\n\\midrule\ndeepseek\\_zero-shot     & $2.3\\!\\times\\!10^{-15}$ & $+0.00\\%$ & $8.1\\!\\times\\!10^{-4}$ & $-0.09\\%$ \\\\\nllama4\\_few-shot-3      & $5.2\\!\\times\\!10^{-15}$ & $+0.00\\%$ & $6.8\\!\\times\\!10^{-4}$ & $-0.07\\%$ \\\\\nllama4\\_few-shot-5      & $4.3\\!\\times\\!10^{-15}$ & $+0.00\\%$ & $6.8\\!\\times\\!10^{-4}$ & $-0.06\\%$ \\\\\nllama4\\_zero-shot       & $1.6\\!\\times\\!10^{-15}$ & $+0.00\\%$ & $5.9\\!\\times\\!10^{-4}$ & $-0.05\\%$ \\\\\nqwen2.5-7b\\_few-shot-3  & $7.2\\!\\times\\!10^{-15}$ & $-0.00\\%$ & $6.8\\!\\times\\!10^{-4}$ & $-0.01\\%$ \\\\\nqwen2.5-7b\\_few-shot-5  & $8.2\\!\\times\\!10^{-15}$ & $+0.00\\%$ & $5.6\\!\\times\\!10^{-4}$ & $+0.05\\%$ \\\\\n\\midrule\n\\textbf{Mean}           & ---                     & $\\mathbf{0.0\\%}$ & ---            & $\\mathbf{-0.04\\%}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTwo findings: (i) Under OLS, $\\hat\\tau_{\\mathrm{corr}}^{(m)}=\\hat\\tau_{\\mathrm{un}}^{(m)}$ to machine precision in every replication, confirming Proposition~\\ref{app:fwl_proof} as an exact algebraic identity. (ii) Under logistic regression, per-replication estimates differ by $|\\Delta|_{\\max}\\!\\sim\\!10^{-3}$---thirteen orders of magnitude larger than the OLS gap---so the invariance fails formally. However, the directional effect on bias is negligible: mean bias reduction is $-0.04\\%$ across the six confusion matrices (range $[-0.09\\%, +0.05\\%]$, not even consistent in sign). Matrix-based corrections remain practically useless under logistic regression---not by an exact invariance, but because the deviation is too small to systematically offset the misclassification-induced bias (which itself is $\\sim\\!0.10$ in absolute units, two orders of magnitude larger than $|\\Delta|$). The routing rule of Algorithm~\\ref{alg:correction} (skip Naive/MLA for these four topologies) is therefore conservative-but-correct under logistic regression as well. Script: \\texttt{artifacts/exp\\_fwl\\_logistic\\_breakdown.py}; results: \\texttt{exp\\_fwl\\_logistic\\_results.json}.\n\n\\subsection{Applied Illustration: ClinicalBERT Case Study}\n\\label{app:case_study}\n\nTo demonstrate the framework's end-to-end utility, we apply it retrospectively to \\citet{lee_wood_doughty2024}, who use ClinicalBERT to classify patient smoking status ($K{=}4$: never, past, current, unknown) from clinical notes and control for this predicted confounder when estimating the causal effect of echocardiography on mortality in 4{,}735 MIMIC-III sepsis patients.\nOur taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.\nThree conclusions follow directly.\nFirst, the zero sign-flip guarantee for confounding (Table~\\ref{tab:taxonomy}) ensures that the estimated protective effect (OR~$= 0.89$) cannot reverse direction due to annotation error---a reassurance unavailable without topology-specific analysis.\nSecond, the FWL invariance result implies that any correction reducing to $C^{-1}$ applied to the dummy-coded confounder achieves exactly 0\\% bias reduction for the treatment coefficient; naive plug-in is provably futile here.\nThird, our correction guidance ranks PPI++ (83.2\\% RMSE reduction for confounding) above MC-SIMEX (35.1\\%) when gold labels are available---a concrete recommendation the original study lacked.\nThis example illustrates the intended workflow: DAG identification $\\to$ topology-specific guarantees $\\to$ correction method selection.\n\n\\subsection{IV Wald Estimator: Diagonal-Dominance Subspaces}\n\\label{sec:iv_dirichlet_subspace}\n\nSection~\\ref{sec:taxonomy_results} reports a 52.6\\% Wald sign-flip rate\nover the full Dirichlet$(1,1,1)$ prior. Because realistic LLM confusion\nmatrices are diagonal-dominant, we replicate the exposure-DAG stratification\nfor the IV topology, restricting the sample\nspace to $\\{C : \\min_k C_{kk} \\geq d\\}$ for $d \\in \\{0, 0.5, 0.7, 0.9\\}$\n(100{,}000 random matrices per threshold).\n\n\\begin{table}[h]\n\\centering\n\\caption{IV Wald estimator bias by minimum-diagonal subspace ($K{=}3$, $\\tau_{\\text{true}}{=}1.41$).\nRates over 100{,}000 Dirichlet-truncated random $C$ per threshold.}\n\\label{tab:iv_dirichlet_subspace}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Subspace} & \\textbf{Violation} & \\textbf{Sign Flip} & \\textbf{Amplif.} & \\textbf{Worst} \\\\\n\\midrule\nFull           & 100.0\\% & 51.7\\% & 48.3\\% & $10^{5}\\!\\times$ \\\\\n$d \\geq 0.5$   & 100.0\\% & 0.0\\%  & 100.0\\% & $28.6\\times$ \\\\\n$d \\geq 0.7$   & 100.0\\% & 0.0\\%  & 100.0\\% & $2.4\\times$ \\\\\n$d \\geq 0.9$   & 100.0\\% & 0.0\\%  & 100.0\\% & $1.2\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe contrast with exposure is instructive: at $d{\\geq}0.7$, exposure violation drops to 13.7\\% (sign reversal 2.1\\%, amplification 11.7\\%), while IV maintains 100\\% violation with pure amplification. IV sign reversal is entirely driven by pathological (near-random) confusion matrices where the Wald denominator crosses zero; diagonal dominance reduces this crossing to near-zero under empirical accuracy conditions but cannot prevent amplification. Even at $d{\\geq}0.9$, the Wald estimator inflates $|\\tau|$ by up to $1.24\\times$ with probability~1.\n\n\\subsection{Non-Differential Misclassification Verification}\n\\label{sec:nondiff_verify}\n\nThe non-differential assumption $P(A^*{=}j \\mid A{=}k, Y, \\mathbf{Z}) = P(A^*{=}j \\mid A{=}k)$ holds \\emph{by design} in standard LLM annotation pipelines: the model receives only source text as input and classifies without observing the outcome $Y$ or covariates $\\mathbf{Z}$. The annotation API call is structurally independent of downstream variables, satisfying the conditional independence requirement.\n\nTo provide empirical support beyond the design argument, we examine topic-stratified confusion matrices using the VAST dataset ($K{=}3$, stance detection), where the \\texttt{topic} field (e.g., ``gun control,'' ``college'') serves as a proxy for latent factors correlated with $Y$. Across 10 model configurations (3 LLMs $\\times$ 2--4 prompt types) and 19 qualifying topics (minimum 10 samples per topic), we compute per-topic confusion matrices $C_{\\text{topic}}(t) = P(A^*{=}j \\mid A{=}k, \\text{topic}{=}t)$ and compare against the overall $C = P(A^*{=}j \\mid A{=}k)$.\n\nPer-topic sample sizes range from 10 to 42, making individual topic CMs inherently noisy. A bootstrap permutation test ($B{=}10{,}000$) under the non-differential null shows that the expected grand maximum deviation $\\max_{t,j,k} |C_{\\text{topic}}(j,k) - C(j,k)|$ at the 95th percentile ranges from 0.90 to 0.98 across model configurations---driven by the smallest topics. For the 5 largest topics ($n \\geq 28$), expected per-topic max deviation at the 95th percentile is 0.38--0.49, consistent with finite-sample variation rather than systematic topic-dependence. The observed per-topic variation is fully consistent with the non-differential null.\n\nThis proxy-based test is necessarily limited: topic is not the actual outcome $Y$, and small per-topic samples reduce statistical power. The design argument (LLM input excludes $Y$) remains the primary justification; the stress test in Section~\\ref{sec:nondiff_stress} below quantifies bias degradation under hypothetical violations.\n\n\\subsection{Non-Differential Assumption Stress Test}\n\\label{sec:nondiff_stress}\n\nOur main analysis assumes non-differential misclassification: the confusion matrix $C$ does not depend on the outcome $Y$. To assess sensitivity to violations of this assumption, we conduct a stress test on the exposure topology ($K{=}3$, $\\min_k C_{kk} \\geq 0.7$, 10{,}000 random matrices per $\\varepsilon$). For each base matrix $C_0$, observations with $Y > \\text{median}(Y)$ are misclassified using a perturbed matrix $\\tilde{C} = \\text{renormalize}(C_0 + \\varepsilon \\cdot \\Delta)$ where $\\Delta_{jk} \\sim \\text{Uniform}(-1,1)$ for $j \\neq k$, while observations with $Y \\leq \\text{median}(Y)$ retain $C_0$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Effect of differential misclassification on bias violation rates (exposure DAG, $K{=}3$, $\\min_k C_{kk} \\geq 0.7$, $N{=}50{,}000$ MC samples per trial).}\n\\label{tab:nondiff_stress}\n\\begin{tabular}{cccc}\n\\toprule\n$\\varepsilon$ & Sign-Flip (\\%) & Amplification (\\%) & Any Violation (\\%) \\\\\n\\midrule\n0.00 & 2.0 & 11.5 & 13.3 \\\\\n0.01 & 2.4 & 12.4 & 14.7 \\\\\n0.05 & 2.8 & 13.0 & 15.7 \\\\\n0.10 & 4.5 & 16.7 & 20.9 \\\\\n0.20 & 9.7 & 23.7 & 32.6 \\\\\n0.30 & 15.5 & 28.7 & 42.8 \\\\\n0.50 & 22.9 & 34.9 & 54.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe $\\varepsilon{=}0$ baseline (13.3\\% violation) closely matches the analytical result (13.7\\%) from Section~\\ref{sec:taxonomy_results}. Small departures ($\\varepsilon \\leq 0.05$) change rates by fewer than 3 percentage points. At $\\varepsilon{=}0.10$, the violation rate increases by 7.6~pp; at $\\varepsilon{=}0.50$, it rises to 54.6\\% (+41.2~pp), indicating substantial sensitivity to large differential error. Our main conclusions hold under mild violations but should be interpreted cautiously when outcome-conditional annotation is suspected.\n\n\\paragraph{Extended stress test.}\nAn extended stress test across 96 configurations (4 topologies $\\times$ 2 $K$ $\\times$ 3 CM qualities $\\times$ 4 $\\varepsilon$, 100 MC replications each; Table~\\ref{tab:stress-test}) confirms these patterns broadly: at $\\varepsilon{=}0$, sign-flip rates are zero for all configurations; at $\\varepsilon{=}0.10$, the maximum sign-flip rate is 7\\% (IV, low-quality $C_{kk}{=}0.4$, $K{=}3$). At $K{=}10$, sign-flip rates remain zero for all topologies and $\\varepsilon$ values, suggesting that higher $K$ provides additional robustness to differential misclassification.\n\n\\input{exp_a_stress_test_table.tex}\n\n\\paragraph{Structured violation models.}\nBeyond uniform perturbations, we compare two structured violation models across all seven topologies ($K{=}3$, 1{,}000 matrices per $\\varepsilon$, $\\min_k C_{kk}{\\geq}0.7$): (1)~\\emph{outcome-conditional}, where $\\tilde{C}$ applies to $Y{>}\\text{median}(Y)$ while $C_0$ applies below; (2)~\\emph{label-specific}, where off-diagonal perturbation magnitude scales with $|\\text{corr}(A{=}k, Y)|$, modeling accuracy degradation on $Y$-predictive categories. For exposure at $\\varepsilon{=}0.20$, label-specific violations are substantially milder than uniform (sign-flip 0.1\\% vs.\\ 10.1\\%), while outcome-conditional violations are more severe (sign-flip 13.9\\%, mean relative bias 0.50 vs.\\ 0.40). All five sign-preserving topologies maintain 0\\% sign-flip under both structured models at all $\\varepsilon$ tested; IV likewise shows 0\\% sign-flip (its vulnerability requires pathological diagonal structure, not differential error). These results indicate that the uniform perturbation model is neither uniformly conservative nor uniformly liberal: practitioners should assess which violation pattern is most plausible for their annotation pipeline.\n\n\\subsection{Robustness to Nonlinear DGP}\n\\label{sec:logistic_dgp}\n\nWe replace the linear structural equations with $Y \\sim \\text{Bernoulli}(\\sigma(\\mathbf{x}^\\top\\boldsymbol{\\beta}))$ and estimate via logistic regression (control function for IV) for all seven topologies, using $K{=}3$, six real VAST confusion matrices, 500 MC replications, and $N{=}10{,}000$. Mean sign-flip rates across the six CMs:\n\n\\begin{center}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule",
      "numLines": 120,
      "startLine": 950,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "abb9488d-a2f2-4ef1-8a2b-e9b6685ed9d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 87 · 2026-05-24T06:38:08.662Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PXRgoWRsu7YbcCrCn1iLRs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 1070,
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "90c4f7ae-3c53-480e-bc50-310fb6c8e5b1",
  "isSidechain": false,
  "requestId": "req_011CbLw2wK9gYkfeGvJtbL1v",
  "type": "assistant",
  "uuid": "ee00c776-6cbb-4a4a-bd59-f7870feb18bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JJyZDrf1MWR9pQYUiwN2ec",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7428,
      "cache_read_input_tokens": 86186,
      "output_tokens": 2178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7428,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2178,
          "cache_read_input_tokens": 86186,
          "cache_creation_input_tokens": 7428,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7428
          },
          "type": "message"
        }
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

_source line 88 · 2026-05-24T06:38:09.005Z_

```json
{
  "parentUuid": "e7b0a4ec-3fce-4773-9935-ce1f25efe3be",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "f5d8f92a-1229-4b41-bfb1-df2de79357de",
  "timestamp": "2026-05-24T06:38:09.005Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 89_

```json
{
  "type": "last-prompt",
  "leafUuid": "f5d8f92a-1229-4b41-bfb1-df2de79357de",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 90_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 91 · 2026-05-24T06:38:11.897Z_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the remaining parts of the appendix (from line 1170 onwards) and the FWL nonlinear section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f5d8f92a-1229-4b41-bfb1-df2de79357de",
  "isSidechain": false,
  "requestId": "req_011CbLw64JBWm3NHHSL8ENXH",
  "type": "assistant",
  "uuid": "c67dbf55-2b17-44f7-a893-aa5f139b583f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011ggM4V99XFRP662wjXcjtK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11571,
      "cache_read_input_tokens": 93614,
      "output_tokens": 172,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11571,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 172,
          "cache_read_input_tokens": 93614,
          "cache_creation_input_tokens": 11571,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11571
          },
          "type": "message"
        }
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

_source line 92 · 2026-05-24T06:38:14.259Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KBwkVWzJrtC7dc5U94nYcd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "offset": 1170,
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c67dbf55-2b17-44f7-a893-aa5f139b583f",
  "isSidechain": false,
  "requestId": "req_011CbLw64JBWm3NHHSL8ENXH",
  "type": "assistant",
  "uuid": "f3ee547b-2475-4fe9-8696-9168ed5fd2d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011ggM4V99XFRP662wjXcjtK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11571,
      "cache_read_input_tokens": 93614,
      "output_tokens": 172,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11571,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 172,
          "cache_read_input_tokens": 93614,
          "cache_creation_input_tokens": 11571,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11571
          },
          "type": "message"
        }
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

_source line 93 · 2026-05-24T06:38:14.263Z_

<details><summary>↩ Tool result · `toolu_01KBwkVWzJrtC7dc5U94nYcd`</summary>

```text
1170	\begin{tabular}{lccccc}
1171	\toprule
1172	\textbf{Topology} & $\tau{=}0.1$ & $\tau{=}0.5$ & $\tau{=}1.0$ & $\tau{=}2.0$ & $\tau{=}5.0$ \\
1173	\midrule
1174	Confounding & \textbf{0.118} (200) & 0.027 (0) & 0.014 (0) & 0.007 (0) & 0.002 (0) \\
1175	Mediation   & \textbf{0.130} (1950) & 0.026 (0) & 0.013 (0) & \textbf{0.112} (1) & 0.003 (0) \\
1176	Collider    & 0.022 (0) & 0.006 (0) & 0.005 (0) & 0.004 (0) & 0.002 (0) \\
1177	Exposure    & \textbf{0.111} (5) & \textbf{0.122} (2) & \textbf{0.152} (2) & \textbf{0.089} (3) & \textbf{0.148} (3) \\
1178	M-bias      & 0.014 (0) & 0.003 (0) & 0.001 (0) & 0.001 (0) & 0.000 (0) \\
1179	Front-door  & 0.003 (0) & 0.013 (0) & 0.027 (0) & 0.051 (0) & \textbf{0.139} (664) \\
1180	\bottomrule
1181	\end{tabular}
1182	\end{table}
1183	
1184	\paragraph{Effect-magnitude sensitivity.}
1185	We further vary the direct effect $\beta \in \{0.1, 0.5, 1.0, 2.0, 5.0\}$ and noise variance $\sigma^2 \in \{0.5, 1.0, 2.0\}$ across all seven topologies ($K{=}3$, 10{,}000 Dirichlet$(1,\ldots,1)$ matrices per cell). Table~\ref{tab:dgp_sensitivity} reports the worst-case relative envelope deviation $\varepsilon_{\text{rel}}$. For non-exposure topologies, $\varepsilon$ scales approximately linearly with $|\beta|$; the safe/fragile partition is stable across all 105 cells.
1186	
1187	\input{conjecture_dgp_sensitivity_table.tex}
1188	
1189	\subsection{Proportional Effects Breakdown}
1190	\label{sec:proportional_effects}
1191	
1192	Theorem~\ref{thm:monotone} requires proportional effects ($f = \lambda g$); here we quantify how $\lambda(C)$ out-of-bounds (OOB) rates depend on the degree of departure from proportionality. We simulate $K{=}3$ mediation with 100{,}000 random confusion matrices (diagonal $\geq 0.5$, Dirichlet off-diagonal) at five proportionality degrees: exact ($f_j {-} f_0 = \lambda(g_j {-} g_0)$), near-proportional ($f = \lambda g + \epsilon$, $\epsilon \sim \mathcal{N}(0,\sigma^2)$, $\sigma \in \{0.1, 0.3, 0.5\}$), and fully independent ($f \perp g$). Table~\ref{tab:proportional_effects} reports the $\lambda(C) \notin [0,1]$ rate.
1193	
1194	\begin{table}[h]
1195	\centering
1196	\small
1197	\caption{$\lambda(C)$ out-of-bounds rate and mediation sign failure rate by degree of departure from proportional effects ($K{=}3$, 100K random confusion matrices per row).}
1198	\label{tab:proportional_effects}
1199	\begin{tabular}{lcc}
1200	\toprule
1201	\textbf{Proportionality degree} & $\lambda(C) \notin [0,1]$ & Sign failure \\
1202	\midrule
1203	Exact ($\sigma{=}0$) & 0.0\% & 0.85\% \\
1204	Near ($\sigma{=}0.1$) & 10.3\% & 0.87\% \\
1205	Near ($\sigma{=}0.3$) & 19.0\% & 0.96\% \\
1206	Near ($\sigma{=}0.5$) & 22.4\% & 0.93\% \\
1207	Independent ($f \perp g$) & 22.9\% & 0.17\% \\
1208	\midrule
1209	NLP-realistic (plan\_006 DGP) & 0.07\% & 0.0\% \\
1210	\bottomrule
1211	\end{tabular}
1212	\end{table}
1213	
1214	The $\lambda$ OOB rate rises steeply from 0\% to ${\sim}10$\% at $\sigma{=}0.1$ and saturates near 23\% for independent $(f,g)$. Sign failure rates remain below 1\% across all conditions because $\lambda$ excursions outside $[0,1]$ are typically small and do not reverse the dominant effect direction. The NLP-realistic DGP ($\delta{=}[0, 0.8, {-}0.6]$, $\beta{=}[0, 1.0, {-}0.5]$) exhibits near-zero OOB (0.07\%) and zero sign failures, confirming that proportional effects hold approximately in practice.
1215	
1216	\subsection{FWL Invariance Under Nonlinear Models}
1217	\label{sec:fwl_nonlinear}
1218	
1219	FWL invariance guarantees exactly 0\% bias reduction from matrix-based corrections (MLA, naive plug-in) under linear OLS for covariate topologies (confounding, mediation, collider, M-bias). Here we test whether this invariance persists under logistic regression across sample sizes $N \in \{1000, 5000, 10{,}000, 50{,}000\}$ and three error levels ($C_{kk} \in \{0.9, 0.7, 0.5\}$), with 200 Monte Carlo replicates per cell. Table~\ref{tab:fwl_nonlinear} reports the mean logistic bias reduction (positive = correction helps).
1220	
1221	\begin{table}[h]
1222	\centering
1223	\small
1224	\caption{Mean logistic bias reduction (\%) from matrix-based correction, by topology and error level (averaged over $N \in \{1K, 5K, 10K, 50K\}$; 200 MC reps each). Under linear OLS, all covariate topologies yield exactly 0\%. Exposure is shown for comparison.}
1225	\label{tab:fwl_nonlinear}
1226	\begin{tabular}{lccc}
1227	\toprule
1228	\textbf{Topology} & \textbf{Low} ($C_{kk}{=}0.9$) & \textbf{Med} ($C_{kk}{=}0.7$) & \textbf{High} ($C_{kk}{=}0.5$) \\
1229	\midrule
1230	Confounding & $-$0.003\% & $<$0.001\% & $<$0.001\% \\
1231	Mediation & $-$0.004\% & $<$0.001\% & $<$0.001\% \\
1232	Collider & $-$0.033\% & $-$0.020\% & $<$0.001\% \\
1233	M-bias & $-$0.049\% & $-$0.010\% & $<$0.001\% \\
1234	Front-door & 0.001\% & $-$0.001\% & $<$0.001\% \\
1235	\midrule
1236	Exposure & $-$68.5\% & $-$48.7\% & $-$22.5\% \\
1237	\bottomrule
1238	\end{tabular}
1239	\end{table}
1240	
1241	For all five covariate topologies, logistic bias reduction is negligible ($|$mean$| < 0.05\%$) across all $N$ and error levels, with no systematic $N$-scaling: medians cluster within $\pm 0.002\%$ at $N{=}50{,}000$. The large standard deviations observed at certain $(N, \text{error})$ cells for collider and M-bias (up to 2.6\% std at $N{=}10{,}000$) reflect rare outlier replicates; medians remain near zero. This confirms that FWL invariance is a robust structural property that extends beyond linear models for covariate topologies.
1242	
1243	In contrast, exposure shows substantial FWL breakdown under logistic regression: $-$22\% to $-$78\% bias reduction (negative = correction worsens bias), stabilising at $N \geq 5{,}000$. The breakdown magnitude increases with accuracy ($C_{kk}$), consistent with the exposure topology's sensitivity to the nonlinear link function transforming category weights.
1244	
1245	\subsection{PPI++ Gold Label Ratio Sensitivity}
1246	\label{sec:ppi_gold_ratio}
1247	
1248	We test PPI++ correction performance as a function of gold label fraction ($K{=}3$, $N{=}10{,}000$, 100 MC replications, 5 Dirichlet confusion matrices with $\min_k C_{kk}{\geq}0.6$).
1249	
1250	\begin{table}[h]
1251	\centering
1252	\small
1253	\caption{PPI++ RMSE reduction (\%) vs.\ gold label fraction across five topologies. Negative values indicate PPI++ increases RMSE relative to the naive estimator.}
1254	\label{tab:ppi_gold_ratio}
1255	\begin{tabular}{lccccc}
1256	\toprule
1257	Topology & 5\% & 10\% & 20\% & 50\% & 100\% \\
1258	\midrule
1259	Confounding & $+$84.8 & $+$88.6 & $+$91.8 & $+$94.2 & $+$95.2 \\
1260	Exposure & $+$75.2 & $+$83.1 & $+$87.1 & $+$91.2 & $+$93.8 \\
1261	Mediation & $+$56.7 & $+$70.4 & $+$77.2 & $+$85.3 & $+$88.7 \\
1262	IV & $+$1.4 & $+$22.1 & $+$50.1 & $+$66.7 & $+$76.4 \\
1263	M-bias & $-$125.3 & $-$43.6 & $-$19.6 & $+$6.0 & $+$18.5 \\
1264	\bottomrule
1265	\end{tabular}
1266	\end{table}
1267	
1268	For confounding and exposure, PPI++ achieves $>$75\% RMSE reduction even at 5\% gold labels; IV requires ${\geq}20\%$ gold to reach 50\% reduction, reflecting the Wald estimator's higher variance. M-bias exhibits harmful correction at ${\leq}20\%$ gold ($-125\%$ at 5\%), because PPI++ re-exposes the M-bias pathway that annotation error had attenuated; only at ${\geq}50\%$ gold does the estimator become weakly beneficial ($+6\%$).
1269	
1270	\subsection{Realistic Differential Misclassification Thresholds}
1271	\label{sec:realistic_epsilon}
1272	
1273	Our non-differential assumption (Definition~\ref{def:nondiff}) requires $P(A^*{\mid}A,Y) = P(A^*{\mid}A)$. We estimate how much $Y$-stratified differential error each of our 23 empirical LLM confusion matrices can tolerate before exposure sign reversal exceeds 5\%. For each matrix $C$, we construct $C_{\text{high}} = \text{renorm}(C + \varepsilon\Delta)$ and $C_{\text{low}} = \text{renorm}(C - \varepsilon\Delta)$ with random off-diagonal perturbation $\Delta$ (500 MC trials per $\varepsilon$), sweep $\varepsilon \in [0, 0.50]$, and report the safe threshold $\varepsilon^*_{\text{safe}} = \max\{\varepsilon : \text{reversal rate} < 5\%\}$ (Table~\ref{tab:realistic_epsilon}).
1274	
1275	\begin{table}[h]
1276	\centering
1277	\small
1278	\caption{Safe differential misclassification thresholds $\varepsilon^*_{\text{safe}}$ by dataset/K. For $K{=}2$ (binary), no configuration produces sign reversal up to $\varepsilon{=}0.50$. For $K{\geq}3$, the majority of configurations are fragile ($\varepsilon^*_{\text{safe}}{=}0$), confirming that the non-differential assumption is load-bearing for multi-class exposure.}
1279	\label{tab:realistic_epsilon}
1280	\begin{tabular}{lccccc}
1281	\toprule
1282	\textbf{Dataset} & $K$ & $n$ & \textbf{Mean} $\varepsilon^*$ & \textbf{Median} $\varepsilon^*$ & $\varepsilon^*{=}0$ \\
1283	\midrule
1284	Civil Comments & 2 & 7 & 0.50 & 0.50 & 0/7 \\
1285	VAST & 3 & 8 & 0.003 & 0.00 & 7/8 \\
1286	HuMAID & 10 & 8 & 0.045 & 0.00 & 7/8 \\
1287	\bottomrule
1288	\end{tabular}
1289	\end{table}
1290	
1291	The distribution is sharply bimodal: all $K{=}2$ configurations are immune to differential misclassification within the tested range ($\varepsilon^*_{\text{safe}}{=}0.50$), consistent with the binary sign-preservation guarantee (Proposition~\ref{prop:signflip}(c)). For $K{\geq}3$, 14 of 16 configurations have $\varepsilon^*_{\text{safe}}{=}0$---sign reversal occurs at the smallest tested $\varepsilon{=}0.01$. Two outliers (VAST: $\varepsilon^*{=}0.02$; HuMAID: $\varepsilon^*{=}0.36$) have atypically structured confusion matrices. This confirms that even small violations of non-differential misclassification are consequential for multi-class exposure, underscoring the practical importance of validating $P(A^*{\mid}A,Y) \approx P(A^*{\mid}A)$ on gold-labeled subsets when $K \geq 3$.
1292	
1293	\subsection{Proportional Effects with Empirical Confusion Matrices}
1294	\label{sec:proportional_real_matrices}
1295	
1296	Theorem~\ref{thm:monotone} assumes proportional effects ($f = \lambda g$). We evaluate this assumption using all 23 empirical LLM confusion matrices under four DGP groups in the mediation topology (23 matrices $\times$ 50 seeds $\times$ 100{,}000 precomputed samples per seed).
1297	
1298	\begin{table}[h]
1299	\centering
1300	\small
1301	\caption{Proportional effects validation with 23 real LLM confusion matrices under mediation DGP. $\lambda(C) \in [0,1]$: proportion satisfying the Theorem~\ref{thm:monotone} bound. Sign pres.: sign preservation rate of the direct effect estimate.}
1302	\label{tab:proportional_empirical}
1303	\begin{tabular}{lcccc}
1304	\toprule
1305	\textbf{DGP Group} & $\lambda(C)$ \textbf{mean} & $\lambda(C) \in [0,1]$ & \textbf{Sign pres.} & \textbf{CV} \\
1306	\midrule
1307	Proportional ($f{=}\lambda g$) & 0.271 & 99.8\% & 100\% & 0.00 \\
1308	Near-prop.\ ($\sigma{=}0.1$) & 0.285 & 99.2\% & 100\% & 1.06 \\
1309	Non-proportional & 0.240 & 85.0\% & 97.3\% & 3.60 \\
1310	Sparse & 0.296 & 75.8\% & 98.6\% & 6.59 \\
1311	\bottomrule
1312	\end{tabular}
1313	\end{table}
1314	
1315	Under proportional and near-proportional effects, $\lambda(C)$ remains within $[0,1]$ for ${\geq}99\%$ of configurations with 100\% sign preservation---the Theorem~\ref{thm:monotone} conditions are satisfied by real LLM confusion matrices. Even under non-proportional effects ($f$ independent of $g$), sign preservation remains at 97.3\%, with $\lambda(C)$ exceeding $[0,1]$ in 15\% of cases. The per-$K$ breakdown shows that $\lambda(C)$ is dimension-dependent: $K{=}2$ (mean 0.249), $K{=}3$ (mean 0.082), $K{=}10$ (mean 0.490), with 100\% in $[0,1]$ across all $K$ under proportional effects. Sparse DGP (zero-effect categories) produces the highest violation rate (24.2\%), consistent with the breakdown mechanism: zero-effect categories make $f/g$ ratios undefined, maximally departing from proportionality.
1316	
1317	\subsection{Case Study: ASV Diagnosis of Political Ad Tone Classification}
1318	\label{sec:asv_case_study}
1319	
1320	We illustrate the ASV diagnostic workflow on a concrete CSS application. \citet{egami_hinck_stewart_wei2023} use LLM classifiers to annotate political advertising tone ($K{=}3$: promote/contrast/attack) from the Fowler \& Ridout database, then estimate the causal effect of ad tone on voter outcomes. The annotated variable is the \textbf{exposure} (treatment). Using a representative $K{=}3$ confusion matrix from our empirical set (VAST DeepSeek zero-shot, mean diagonal 0.734) as a proxy:
1321	
1322	\begin{center}
1323	\small
1324	\begin{tabular}{lccc}
1325	\toprule
1326	Coefficient & $\delta^*_{\text{mag}}$ (10\%) & $\delta^*_{\text{sf}}$ & Relative bias at $\delta{=}1$ \\
1327	\midrule
1328	$\beta_1$ (primary) & 0.234 & $> 1.5$ & 39.7\% \\
1329	$\beta_2$ (secondary) & 0.154 & $> 1.5$ & 60.4\% \\
1330	\bottomrule
1331	\end{tabular}
1332	\end{center}
1333	
1334	Both coefficients are magnitude-unsafe ($\delta^* < 1$), with the secondary coefficient more fragile ($\delta^*{=}0.154$). If the same annotator were instead classifying a \textbf{confounder} (e.g., media framing as a control variable), magnitude ASV rises to $\delta^*{=}0.690$---a $3{\times}$ increase in error tolerance from the same confusion matrix. This demonstrates the central insight: topology, not annotator quality, determines vulnerability. Algorithm~\ref{alg:correction} routes this exposure topology to PPI++ or DSL correction; matrix-based methods (naive plug-in, MLA) are ineffective due to FWL non-applicability.
1335	
1336	\subsection{End-to-End Demonstration}
1337	\label{sec:e2e_demo}
1338	
1339	\input{e2e_demo_table.tex}
1340	
1341	The demonstration uses a symmetric $C_0$ ($d_{\mathrm{rel}}{=}0$); empirical $K{=}3$ matrices deviate substantially (median $d_{\mathrm{rel}}{=}0.33$, Remark~\ref{rem:symmetry}), but core ASV ranking and correction routing remain valid under Conjecture~\ref{conj:monotone}.
1342	
1343	\subsection{Semi-Real Case Study with Production LLM Confusion Matrices}
1344	\label{sec:real_cm_demo}
1345	
1346	We repeat the end-to-end pipeline using 10 confusion matrices estimated from production LLM annotation of VAST stance detection ($K{=}3$; DeepSeek, Llama4, Qwen2.5-7B, Qwen3 under zero-shot and few-shot prompting). These matrices exhibit median $d_{\mathrm{rel}}{=}0.33$ (Remark~\ref{rem:symmetry}), far from the symmetric assumption of Theorem~\ref{thm:k3_symmetric}. Results confirm both topology-dependent patterns: PPI++ achieves 93.6\% median exposure bias reduction while plug-in corrections yield 0\% improvement for confounding (FWL invariance, machine precision; Table~\ref{tab:e2e-real-cm}).
1347	
1348	\input{e2e_real_cm_table.tex}
1349	
1350	\subsection{Correction Method Sensitivity to $K$}
1351	\label{sec:correction_k_sensitivity}
1352	
1353	We test whether the correction method ranking from Table~\ref{tab:correction} ($K{=}3$) is stable at $K{=}5$ and $K{=}10$. For each $K$, we sample 5 random Dirichlet confusion matrices (diagonal $\geq 0.6$), run 100 MC replications per topology--matrix combination ($N{=}5{,}000$, 10\% gold fraction), and compute RMSE reduction for all five methods across all seven topologies.
1354	
1355	\paragraph{Grand ranking stability.}
1356	Spearman rank correlations across all topology--method pairs: $\rho_{3,5} = 0.80$, $\rho_{3,10} = 0.84$, $\rho_{5,10} = 0.93$ (all $p < 10^{-8}$). Per-topology correlations are even stronger: 5 of 7 topologies (confounding, collider, M-bias, IV, and exposure at $K{=}10$) achieve $\rho = 1.0$ between $K{=}3$ and $K{=}10$.
1357	
1358	\paragraph{Method-specific patterns.}
1359	PPI++ effectiveness degrades with $K$: confounding RMSE reduction drops from 85.6\% ($K{=}3$) to 75.6\% ($K{=}10$); mediation drops from 57.1\% to 9.0\%. At $K{=}10$, PPI++ becomes harmful for IV ($-124\%$) and exposure ($-11\%$). MC-SIMEX is the most $K$-robust method, maintaining the top rank for 5/7 topologies at $K{=}10$ (vs.\ 3/7 at $K{=}3$). FWL invariance (naive plug-in and MLA achieving 0\% bias reduction on the treatment coefficient) holds at all $K$ tested, confirming the structural nature of this result.
1360	
1361	\begin{table}[h]
1362	\centering
1363	\small
1364	\caption{Top correction method and RMSE reduction (\%) by topology across $K$. Bold = top method for that topology--$K$ combination.}
1365	\label{tab:correction_k}
1366	\begin{tabular}{lccc}
1367	\toprule
1368	\textbf{Topology} & $K{=}3$ & $K{=}5$ & $K{=}10$ \\
1369	\midrule
1370	Confounding & \textbf{PPI++} 85.6 & \textbf{PPI++} 76.4 & \textbf{PPI++} 75.6 \\
1371	Mediation & \textbf{PPI++} 57.1 & \textbf{SIMEX} 59.7 & \textbf{SIMEX} 59.0 \\
1372	Collider & \textbf{SIMEX} 55.4 & \textbf{SIMEX} 63.4 & \textbf{SIMEX} 57.3 \\
1373	Exposure & \textbf{SIMEX} 72.5 & \textbf{SIMEX} 65.0 & \textbf{SIMEX} 47.3 \\
1374	M-bias & \textbf{SIMEX} 3.2 & \textbf{SIMEX} 47.0 & \textbf{SIMEX} 43.7 \\
1375	IV & \textbf{SIMEX} 30.9 & \textbf{SIMEX} 30.4 & \textbf{SIMEX} 27.1 \\
1376	Front-door & \textbf{PPI++} 82.9 & \textbf{PPI++} 69.0 & \textbf{SIMEX} 70.1 \\
1377	\bottomrule
1378	\end{tabular}
1379	\end{table}
1380	
1381	\subsection{Comparison with Related Sensitivity Frameworks}
1382	\label{sec:sensitivity_comparison}
1383	
1384	\begin{table}[h]
1385	\centering
1386	\caption{Comparison of sensitivity frameworks.}
1387	\label{tab:sensitivity_comparison}
1388	\small
1389	\begin{tabular}{lccc}
1390	\toprule
1391	& \textbf{ASV} & \textbf{E-value} & \textbf{Partial} $R^2$ \\
1392	\midrule
1393	Parameter space & $K{\times}K$ confusion $C(\delta)$ & Scalar confounder & $R^2$ of omitted var \\
1394	Sensitivity path & $(1{-}\delta)I + \delta C_0$ & Monotone scalar & Monotone scalar \\
1395	Topology-specific & \checkmark & \ding{55} & \ding{55} \\
1396	Sign-flip diagnostic & \checkmark ($\delta^*_{\text{sign}}$) & \ding{55} & \ding{55} \\
1397	Topology dependence & \checkmark (7 topologies ranked) & \ding{55} & \ding{55} \\
1398	Monotonicity & Proved $K{=}2$; conj.\ $K{\geq}3$ & Guaranteed & Guaranteed \\
1399	Target & Annotation error & Unmeasured confounding & Omitted variable \\
1400	\bottomrule
1401	\end{tabular}
1402	\end{table}
1403	
1404	\subsection{Per-Topology $F_1$--Bias Correlation}
1405	\label{sec:within_topo_f1}
1406	
1407	The cross-topology correlation between macro $F_1$ and $|\text{bias}|$ is weak ($\rho = -0.10$, $p = 0.45$; \S\ref{sec:empirical}), but decomposing by topology reveals a structured pattern. Table~\ref{tab:within_topo_f1} reports Spearman correlations computed over 23 LLM configurations (HumAID $K{=}10$, VAST $K{=}3$, CivilComments $K{=}2$; 161 total scenarios).
1408	
1409	\begin{table}[h]
1410	\centering
1411	\small
1412	\caption{Within-topology Spearman $\rho(F_1, |\text{bias}|)$ across 23 empirical LLM configurations $\times$ 3 datasets. Negative $\rho$: higher $F_1$ $\to$ lower bias (expected). Positive $\rho$: higher $F_1$ $\to$ higher bias (protective attenuation removed).}
1413	\label{tab:within_topo_f1}
1414	\begin{tabular}{lccc}
1415	\toprule
1416	\textbf{Topology} & $n$ & $\rho$ & $p$ \\
1417	\midrule
1418	Confounding & 23 & $-0.557$ & 0.006 \\
1419	Mediation & 23 & $-0.565$ & 0.005 \\
1420	Exposure & 23 & $-0.531$ & 0.009 \\
1421	Front-door & 23 & $-0.568$ & 0.005 \\
1422	IV & 23 & $-0.700$ & $<$0.001 \\
1423	Collider & 23 & $+0.310$ & 0.150 \\
1424	M-bias & 23 & $+0.867$ & $<$0.001 \\
1425	\bottomrule
1426	\end{tabular}
1427	\end{table}
1428	
1429	Five topologies show the expected negative correlation: better annotation quality ($F_1{\uparrow}$) reduces causal bias. IV shows the strongest effect ($\rho = -0.70$), consistent with the Wald estimator's sensitivity to misclassification in the first stage. M-bias uniquely reverses: $\rho = +0.87$ ($p < 0.001$). The mechanism is that misclassification attenuates the spurious M-bias path, so the naive estimator under noisy annotations is \emph{closer} to the true causal effect; improving annotation quality (higher $F_1$) removes this protective attenuation and \emph{increases} bias. This is consistent with the correction results (\S\ref{sec:correction}), where PPI++ harms M-bias ($-$88\%) by removing the same protective noise. Collider shows a positive but non-significant trend ($\rho = +0.31$, $p = 0.15$), consistent with Berkson bias attenuation. Per-dataset breakdowns (CivilComments $K{=}2$: $\rho = -1.0$ for all topologies with $n{=}7$) should be interpreted with caution given the small sample and limited $F_1$ variation within the binary task.
1430	
1431	\subsection{Confusion Matrix Estimation Robustness}
1432	\label{sec:c_robustness}
1433	
1434	The ASV framework requires the confusion matrix $C$, which in practice must be estimated from a held-out gold-labeled subset. We assess how estimation noise in $\hat{C}$ propagates to the safe/fragile partition and ASV ranking. For each of 8 empirical confusion matrices (VAST, 4 LLMs $\times$ 2 prompting strategies), we draw $n_{\text{gold}} \in \{50, 100, 200, 500\}$ samples from a $\text{Multinomial}(n_{\text{gold}}, C_{\cdot k})$ distribution per column, compute $\hat{C}$, and evaluate the resulting ASV ranking across 200 bootstrap replicates.
1435	
1436	\begin{table}[h]
1437	\centering
1438	\small
1439	\caption{$\hat{C}$ estimation robustness: safe/fragile partition stability and ASV ranking correlation (Spearman $\rho$ vs.\ true-$C$ ranking) under multinomial bootstrap from finite gold sets. 8 empirical matrices $\times$ 200 bootstrap replicates per $n_{\text{gold}}$.}
1440	\label{tab:c_robustness}
1441	\begin{tabular}{lccc}
1442	\toprule
1443	$n_{\text{gold}}$ & Partition stability & $\rho$ (median) & $\rho$ ($q_{25}$) \\
1444	\midrule
1445	50 & 50.4\% & 0.991 & 0.789 \\
1446	100 & 82.0\% & 1.000 & 0.991 \\
1447	200 & 85.6\% & 1.000 & 0.991 \\
1448	500 & 88.5\% & 1.000 & 0.991 \\
1449	\bottomrule
1450	\end{tabular}
1451	\end{table}
1452	
1453	The ASV ranking is highly robust: median Spearman $\rho \geq 0.99$ even at $n_{\text{gold}}{=}50$. The safe/fragile partition (5 safe vs.\ 2 fragile topologies) recovers reliably from $n_{\text{gold}} \geq 100$ (82\% stability), increasing to 89\% at $n_{\text{gold}}{=}500$. The remaining instability concentrates in source matrices with low diagonal dominance (e.g., VAST DeepSeek few-shot: $\min C_{kk} = 0.16$), where bootstrap noise can shift borderline ASV values across the partition boundary. All 8 truth partitions match the canonical safe/fragile partition, confirming that the theoretical dichotomy holds empirically.
1454	
1455	\subsection{Sign Reversal Determinants}
1456	\label{sec:sign_determinants}
1457	
1458	We investigate which confusion matrix features predict exposure sign reversal across the 23 empirical LLM configurations. For each matrix, we compute 10 structural features: $\min_k C_{kk}$ (minimum diagonal), $\overline{C_{kk}}$ (mean diagonal), $\max_{j \neq k} C_{jk}$ (maximum off-diagonal), $\max_{j \neq k} C_{jk}/C_{kk}$ (off-diagonal ratio), $\log(\kappa(C))$ (log condition number), mean and max column entropy, spectral gap, $\det(C)$, and minimum singular value. Sign reversal is defined as any exposure coefficient reversing sign under misclassification.
1459	
1460	\begin{table}[h]
1461	\centering
1462	\small
1463	\caption{Sign reversal rates by $K$ and best single-feature decision rule. Rule: $\det(C) < 0.014 \to$ sign reversal (accuracy 91.3\%, sensitivity 85.7\%, specificity 100\%). An AND rule ($\min_k C_{kk} < 0.55$ and mean entropy $> 0.40$) achieves 95.7\% accuracy with 100\% sensitivity.}
1464	\label{tab:sign_determinants}
1465	\begin{tabular}{lcc}
1466	\toprule
1467	$K$ & $n$ & Sign reversal rate \\
1468	\midrule
1469	2 & 7 & 0/7 (0\%) \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f3ee547b-2475-4fe9-8696-9168ed5fd2d4",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "e16b0729-447d-4592-aa84-06a13394e7c6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
      "content": "\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Topology} & $\\tau{=}0.1$ & $\\tau{=}0.5$ & $\\tau{=}1.0$ & $\\tau{=}2.0$ & $\\tau{=}5.0$ \\\\\n\\midrule\nConfounding & \\textbf{0.118} (200) & 0.027 (0) & 0.014 (0) & 0.007 (0) & 0.002 (0) \\\\\nMediation   & \\textbf{0.130} (1950) & 0.026 (0) & 0.013 (0) & \\textbf{0.112} (1) & 0.003 (0) \\\\\nCollider    & 0.022 (0) & 0.006 (0) & 0.005 (0) & 0.004 (0) & 0.002 (0) \\\\\nExposure    & \\textbf{0.111} (5) & \\textbf{0.122} (2) & \\textbf{0.152} (2) & \\textbf{0.089} (3) & \\textbf{0.148} (3) \\\\\nM-bias      & 0.014 (0) & 0.003 (0) & 0.001 (0) & 0.001 (0) & 0.000 (0) \\\\\nFront-door  & 0.003 (0) & 0.013 (0) & 0.027 (0) & 0.051 (0) & \\textbf{0.139} (664) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Effect-magnitude sensitivity.}\nWe further vary the direct effect $\\beta \\in \\{0.1, 0.5, 1.0, 2.0, 5.0\\}$ and noise variance $\\sigma^2 \\in \\{0.5, 1.0, 2.0\\}$ across all seven topologies ($K{=}3$, 10{,}000 Dirichlet$(1,\\ldots,1)$ matrices per cell). Table~\\ref{tab:dgp_sensitivity} reports the worst-case relative envelope deviation $\\varepsilon_{\\text{rel}}$. For non-exposure topologies, $\\varepsilon$ scales approximately linearly with $|\\beta|$; the safe/fragile partition is stable across all 105 cells.\n\n\\input{conjecture_dgp_sensitivity_table.tex}\n\n\\subsection{Proportional Effects Breakdown}\n\\label{sec:proportional_effects}\n\nTheorem~\\ref{thm:monotone} requires proportional effects ($f = \\lambda g$); here we quantify how $\\lambda(C)$ out-of-bounds (OOB) rates depend on the degree of departure from proportionality. We simulate $K{=}3$ mediation with 100{,}000 random confusion matrices (diagonal $\\geq 0.5$, Dirichlet off-diagonal) at five proportionality degrees: exact ($f_j {-} f_0 = \\lambda(g_j {-} g_0)$), near-proportional ($f = \\lambda g + \\epsilon$, $\\epsilon \\sim \\mathcal{N}(0,\\sigma^2)$, $\\sigma \\in \\{0.1, 0.3, 0.5\\}$), and fully independent ($f \\perp g$). Table~\\ref{tab:proportional_effects} reports the $\\lambda(C) \\notin [0,1]$ rate.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{$\\lambda(C)$ out-of-bounds rate and mediation sign failure rate by degree of departure from proportional effects ($K{=}3$, 100K random confusion matrices per row).}\n\\label{tab:proportional_effects}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Proportionality degree} & $\\lambda(C) \\notin [0,1]$ & Sign failure \\\\\n\\midrule\nExact ($\\sigma{=}0$) & 0.0\\% & 0.85\\% \\\\\nNear ($\\sigma{=}0.1$) & 10.3\\% & 0.87\\% \\\\\nNear ($\\sigma{=}0.3$) & 19.0\\% & 0.96\\% \\\\\nNear ($\\sigma{=}0.5$) & 22.4\\% & 0.93\\% \\\\\nIndependent ($f \\perp g$) & 22.9\\% & 0.17\\% \\\\\n\\midrule\nNLP-realistic (plan\\_006 DGP) & 0.07\\% & 0.0\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe $\\lambda$ OOB rate rises steeply from 0\\% to ${\\sim}10$\\% at $\\sigma{=}0.1$ and saturates near 23\\% for independent $(f,g)$. Sign failure rates remain below 1\\% across all conditions because $\\lambda$ excursions outside $[0,1]$ are typically small and do not reverse the dominant effect direction. The NLP-realistic DGP ($\\delta{=}[0, 0.8, {-}0.6]$, $\\beta{=}[0, 1.0, {-}0.5]$) exhibits near-zero OOB (0.07\\%) and zero sign failures, confirming that proportional effects hold approximately in practice.\n\n\\subsection{FWL Invariance Under Nonlinear Models}\n\\label{sec:fwl_nonlinear}\n\nFWL invariance guarantees exactly 0\\% bias reduction from matrix-based corrections (MLA, naive plug-in) under linear OLS for covariate topologies (confounding, mediation, collider, M-bias). Here we test whether this invariance persists under logistic regression across sample sizes $N \\in \\{1000, 5000, 10{,}000, 50{,}000\\}$ and three error levels ($C_{kk} \\in \\{0.9, 0.7, 0.5\\}$), with 200 Monte Carlo replicates per cell. Table~\\ref{tab:fwl_nonlinear} reports the mean logistic bias reduction (positive = correction helps).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Mean logistic bias reduction (\\%) from matrix-based correction, by topology and error level (averaged over $N \\in \\{1K, 5K, 10K, 50K\\}$; 200 MC reps each). Under linear OLS, all covariate topologies yield exactly 0\\%. Exposure is shown for comparison.}\n\\label{tab:fwl_nonlinear}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Topology} & \\textbf{Low} ($C_{kk}{=}0.9$) & \\textbf{Med} ($C_{kk}{=}0.7$) & \\textbf{High} ($C_{kk}{=}0.5$) \\\\\n\\midrule\nConfounding & $-$0.003\\% & $<$0.001\\% & $<$0.001\\% \\\\\nMediation & $-$0.004\\% & $<$0.001\\% & $<$0.001\\% \\\\\nCollider & $-$0.033\\% & $-$0.020\\% & $<$0.001\\% \\\\\nM-bias & $-$0.049\\% & $-$0.010\\% & $<$0.001\\% \\\\\nFront-door & 0.001\\% & $-$0.001\\% & $<$0.001\\% \\\\\n\\midrule\nExposure & $-$68.5\\% & $-$48.7\\% & $-$22.5\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor all five covariate topologies, logistic bias reduction is negligible ($|$mean$| < 0.05\\%$) across all $N$ and error levels, with no systematic $N$-scaling: medians cluster within $\\pm 0.002\\%$ at $N{=}50{,}000$. The large standard deviations observed at certain $(N, \\text{error})$ cells for collider and M-bias (up to 2.6\\% std at $N{=}10{,}000$) reflect rare outlier replicates; medians remain near zero. This confirms that FWL invariance is a robust structural property that extends beyond linear models for covariate topologies.\n\nIn contrast, exposure shows substantial FWL breakdown under logistic regression: $-$22\\% to $-$78\\% bias reduction (negative = correction worsens bias), stabilising at $N \\geq 5{,}000$. The breakdown magnitude increases with accuracy ($C_{kk}$), consistent with the exposure topology's sensitivity to the nonlinear link function transforming category weights.\n\n\\subsection{PPI++ Gold Label Ratio Sensitivity}\n\\label{sec:ppi_gold_ratio}\n\nWe test PPI++ correction performance as a function of gold label fraction ($K{=}3$, $N{=}10{,}000$, 100 MC replications, 5 Dirichlet confusion matrices with $\\min_k C_{kk}{\\geq}0.6$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{PPI++ RMSE reduction (\\%) vs.\\ gold label fraction across five topologies. Negative values indicate PPI++ increases RMSE relative to the naive estimator.}\n\\label{tab:ppi_gold_ratio}\n\\begin{tabular}{lccccc}\n\\toprule\nTopology & 5\\% & 10\\% & 20\\% & 50\\% & 100\\% \\\\\n\\midrule\nConfounding & $+$84.8 & $+$88.6 & $+$91.8 & $+$94.2 & $+$95.2 \\\\\nExposure & $+$75.2 & $+$83.1 & $+$87.1 & $+$91.2 & $+$93.8 \\\\\nMediation & $+$56.7 & $+$70.4 & $+$77.2 & $+$85.3 & $+$88.7 \\\\\nIV & $+$1.4 & $+$22.1 & $+$50.1 & $+$66.7 & $+$76.4 \\\\\nM-bias & $-$125.3 & $-$43.6 & $-$19.6 & $+$6.0 & $+$18.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFor confounding and exposure, PPI++ achieves $>$75\\% RMSE reduction even at 5\\% gold labels; IV requires ${\\geq}20\\%$ gold to reach 50\\% reduction, reflecting the Wald estimator's higher variance. M-bias exhibits harmful correction at ${\\leq}20\\%$ gold ($-125\\%$ at 5\\%), because PPI++ re-exposes the M-bias pathway that annotation error had attenuated; only at ${\\geq}50\\%$ gold does the estimator become weakly beneficial ($+6\\%$).\n\n\\subsection{Realistic Differential Misclassification Thresholds}\n\\label{sec:realistic_epsilon}\n\nOur non-differential assumption (Definition~\\ref{def:nondiff}) requires $P(A^*{\\mid}A,Y) = P(A^*{\\mid}A)$. We estimate how much $Y$-stratified differential error each of our 23 empirical LLM confusion matrices can tolerate before exposure sign reversal exceeds 5\\%. For each matrix $C$, we construct $C_{\\text{high}} = \\text{renorm}(C + \\varepsilon\\Delta)$ and $C_{\\text{low}} = \\text{renorm}(C - \\varepsilon\\Delta)$ with random off-diagonal perturbation $\\Delta$ (500 MC trials per $\\varepsilon$), sweep $\\varepsilon \\in [0, 0.50]$, and report the safe threshold $\\varepsilon^*_{\\text{safe}} = \\max\\{\\varepsilon : \\text{reversal rate} < 5\\%\\}$ (Table~\\ref{tab:realistic_epsilon}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Safe differential misclassification thresholds $\\varepsilon^*_{\\text{safe}}$ by dataset/K. For $K{=}2$ (binary), no configuration produces sign reversal up to $\\varepsilon{=}0.50$. For $K{\\geq}3$, the majority of configurations are fragile ($\\varepsilon^*_{\\text{safe}}{=}0$), confirming that the non-differential assumption is load-bearing for multi-class exposure.}\n\\label{tab:realistic_epsilon}\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Dataset} & $K$ & $n$ & \\textbf{Mean} $\\varepsilon^*$ & \\textbf{Median} $\\varepsilon^*$ & $\\varepsilon^*{=}0$ \\\\\n\\midrule\nCivil Comments & 2 & 7 & 0.50 & 0.50 & 0/7 \\\\\nVAST & 3 & 8 & 0.003 & 0.00 & 7/8 \\\\\nHuMAID & 10 & 8 & 0.045 & 0.00 & 7/8 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe distribution is sharply bimodal: all $K{=}2$ configurations are immune to differential misclassification within the tested range ($\\varepsilon^*_{\\text{safe}}{=}0.50$), consistent with the binary sign-preservation guarantee (Proposition~\\ref{prop:signflip}(c)). For $K{\\geq}3$, 14 of 16 configurations have $\\varepsilon^*_{\\text{safe}}{=}0$---sign reversal occurs at the smallest tested $\\varepsilon{=}0.01$. Two outliers (VAST: $\\varepsilon^*{=}0.02$; HuMAID: $\\varepsilon^*{=}0.36$) have atypically structured confusion matrices. This confirms that even small violations of non-differential misclassification are consequential for multi-class exposure, underscoring the practical importance of validating $P(A^*{\\mid}A,Y) \\approx P(A^*{\\mid}A)$ on gold-labeled subsets when $K \\geq 3$.\n\n\\subsection{Proportional Effects with Empirical Confusion Matrices}\n\\label{sec:proportional_real_matrices}\n\nTheorem~\\ref{thm:monotone} assumes proportional effects ($f = \\lambda g$). We evaluate this assumption using all 23 empirical LLM confusion matrices under four DGP groups in the mediation topology (23 matrices $\\times$ 50 seeds $\\times$ 100{,}000 precomputed samples per seed).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Proportional effects validation with 23 real LLM confusion matrices under mediation DGP. $\\lambda(C) \\in [0,1]$: proportion satisfying the Theorem~\\ref{thm:monotone} bound. Sign pres.: sign preservation rate of the direct effect estimate.}\n\\label{tab:proportional_empirical}\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{DGP Group} & $\\lambda(C)$ \\textbf{mean} & $\\lambda(C) \\in [0,1]$ & \\textbf{Sign pres.} & \\textbf{CV} \\\\\n\\midrule\nProportional ($f{=}\\lambda g$) & 0.271 & 99.8\\% & 100\\% & 0.00 \\\\\nNear-prop.\\ ($\\sigma{=}0.1$) & 0.285 & 99.2\\% & 100\\% & 1.06 \\\\\nNon-proportional & 0.240 & 85.0\\% & 97.3\\% & 3.60 \\\\\nSparse & 0.296 & 75.8\\% & 98.6\\% & 6.59 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nUnder proportional and near-proportional effects, $\\lambda(C)$ remains within $[0,1]$ for ${\\geq}99\\%$ of configurations with 100\\% sign preservation---the Theorem~\\ref{thm:monotone} conditions are satisfied by real LLM confusion matrices. Even under non-proportional effects ($f$ independent of $g$), sign preservation remains at 97.3\\%, with $\\lambda(C)$ exceeding $[0,1]$ in 15\\% of cases. The per-$K$ breakdown shows that $\\lambda(C)$ is dimension-dependent: $K{=}2$ (mean 0.249), $K{=}3$ (mean 0.082), $K{=}10$ (mean 0.490), with 100\\% in $[0,1]$ across all $K$ under proportional effects. Sparse DGP (zero-effect categories) produces the highest violation rate (24.2\\%), consistent with the breakdown mechanism: zero-effect categories make $f/g$ ratios undefined, maximally departing from proportionality.\n\n\\subsection{Case Study: ASV Diagnosis of Political Ad Tone Classification}\n\\label{sec:asv_case_study}\n\nWe illustrate the ASV diagnostic workflow on a concrete CSS application. \\citet{egami_hinck_stewart_wei2023} use LLM classifiers to annotate political advertising tone ($K{=}3$: promote/contrast/attack) from the Fowler \\& Ridout database, then estimate the causal effect of ad tone on voter outcomes. The annotated variable is the \\textbf{exposure} (treatment). Using a representative $K{=}3$ confusion matrix from our empirical set (VAST DeepSeek zero-shot, mean diagonal 0.734) as a proxy:\n\n\\begin{center}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nCoefficient & $\\delta^*_{\\text{mag}}$ (10\\%) & $\\delta^*_{\\text{sf}}$ & Relative bias at $\\delta{=}1$ \\\\\n\\midrule\n$\\beta_1$ (primary) & 0.234 & $> 1.5$ & 39.7\\% \\\\\n$\\beta_2$ (secondary) & 0.154 & $> 1.5$ & 60.4\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{center}\n\nBoth coefficients are magnitude-unsafe ($\\delta^* < 1$), with the secondary coefficient more fragile ($\\delta^*{=}0.154$). If the same annotator were instead classifying a \\textbf{confounder} (e.g., media framing as a control variable), magnitude ASV rises to $\\delta^*{=}0.690$---a $3{\\times}$ increase in error tolerance from the same confusion matrix. This demonstrates the central insight: topology, not annotator quality, determines vulnerability. Algorithm~\\ref{alg:correction} routes this exposure topology to PPI++ or DSL correction; matrix-based methods (naive plug-in, MLA) are ineffective due to FWL non-applicability.\n\n\\subsection{End-to-End Demonstration}\n\\label{sec:e2e_demo}\n\n\\input{e2e_demo_table.tex}\n\nThe demonstration uses a symmetric $C_0$ ($d_{\\mathrm{rel}}{=}0$); empirical $K{=}3$ matrices deviate substantially (median $d_{\\mathrm{rel}}{=}0.33$, Remark~\\ref{rem:symmetry}), but core ASV ranking and correction routing remain valid under Conjecture~\\ref{conj:monotone}.\n\n\\subsection{Semi-Real Case Study with Production LLM Confusion Matrices}\n\\label{sec:real_cm_demo}\n\nWe repeat the end-to-end pipeline using 10 confusion matrices estimated from production LLM annotation of VAST stance detection ($K{=}3$; DeepSeek, Llama4, Qwen2.5-7B, Qwen3 under zero-shot and few-shot prompting). These matrices exhibit median $d_{\\mathrm{rel}}{=}0.33$ (Remark~\\ref{rem:symmetry}), far from the symmetric assumption of Theorem~\\ref{thm:k3_symmetric}. Results confirm both topology-dependent patterns: PPI++ achieves 93.6\\% median exposure bias reduction while plug-in corrections yield 0\\% improvement for confounding (FWL invariance, machine precision; Table~\\ref{tab:e2e-real-cm}).\n\n\\input{e2e_real_cm_table.tex}\n\n\\subsection{Correction Method Sensitivity to $K$}\n\\label{sec:correction_k_sensitivity}\n\nWe test whether the correction method ranking from Table~\\ref{tab:correction} ($K{=}3$) is stable at $K{=}5$ and $K{=}10$. For each $K$, we sample 5 random Dirichlet confusion matrices (diagonal $\\geq 0.6$), run 100 MC replications per topology--matrix combination ($N{=}5{,}000$, 10\\% gold fraction), and compute RMSE reduction for all five methods across all seven topologies.\n\n\\paragraph{Grand ranking stability.}\nSpearman rank correlations across all topology--method pairs: $\\rho_{3,5} = 0.80$, $\\rho_{3,10} = 0.84$, $\\rho_{5,10} = 0.93$ (all $p < 10^{-8}$). Per-topology correlations are even stronger: 5 of 7 topologies (confounding, collider, M-bias, IV, and exposure at $K{=}10$) achieve $\\rho = 1.0$ between $K{=}3$ and $K{=}10$.\n\n\\paragraph{Method-specific patterns.}\nPPI++ effectiveness degrades with $K$: confounding RMSE reduction drops from 85.6\\% ($K{=}3$) to 75.6\\% ($K{=}10$); mediation drops from 57.1\\% to 9.0\\%. At $K{=}10$, PPI++ becomes harmful for IV ($-124\\%$) and exposure ($-11\\%$). MC-SIMEX is the most $K$-robust method, maintaining the top rank for 5/7 topologies at $K{=}10$ (vs.\\ 3/7 at $K{=}3$). FWL invariance (naive plug-in and MLA achieving 0\\% bias reduction on the treatment coefficient) holds at all $K$ tested, confirming the structural nature of this result.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Top correction method and RMSE reduction (\\%) by topology across $K$. Bold = top method for that topology--$K$ combination.}\n\\label{tab:correction_k}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Topology} & $K{=}3$ & $K{=}5$ & $K{=}10$ \\\\\n\\midrule\nConfounding & \\textbf{PPI++} 85.6 & \\textbf{PPI++} 76.4 & \\textbf{PPI++} 75.6 \\\\\nMediation & \\textbf{PPI++} 57.1 & \\textbf{SIMEX} 59.7 & \\textbf{SIMEX} 59.0 \\\\\nCollider & \\textbf{SIMEX} 55.4 & \\textbf{SIMEX} 63.4 & \\textbf{SIMEX} 57.3 \\\\\nExposure & \\textbf{SIMEX} 72.5 & \\textbf{SIMEX} 65.0 & \\textbf{SIMEX} 47.3 \\\\\nM-bias & \\textbf{SIMEX} 3.2 & \\textbf{SIMEX} 47.0 & \\textbf{SIMEX} 43.7 \\\\\nIV & \\textbf{SIMEX} 30.9 & \\textbf{SIMEX} 30.4 & \\textbf{SIMEX} 27.1 \\\\\nFront-door & \\textbf{PPI++} 82.9 & \\textbf{PPI++} 69.0 & \\textbf{SIMEX} 70.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Comparison with Related Sensitivity Frameworks}\n\\label{sec:sensitivity_comparison}\n\n\\begin{table}[h]\n\\centering\n\\caption{Comparison of sensitivity frameworks.}\n\\label{tab:sensitivity_comparison}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n& \\textbf{ASV} & \\textbf{E-value} & \\textbf{Partial} $R^2$ \\\\\n\\midrule\nParameter space & $K{\\times}K$ confusion $C(\\delta)$ & Scalar confounder & $R^2$ of omitted var \\\\\nSensitivity path & $(1{-}\\delta)I + \\delta C_0$ & Monotone scalar & Monotone scalar \\\\\nTopology-specific & \\checkmark & \\ding{55} & \\ding{55} \\\\\nSign-flip diagnostic & \\checkmark ($\\delta^*_{\\text{sign}}$) & \\ding{55} & \\ding{55} \\\\\nTopology dependence & \\checkmark (7 topologies ranked) & \\ding{55} & \\ding{55} \\\\\nMonotonicity & Proved $K{=}2$; conj.\\ $K{\\geq}3$ & Guaranteed & Guaranteed \\\\\nTarget & Annotation error & Unmeasured confounding & Omitted variable \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Per-Topology $F_1$--Bias Correlation}\n\\label{sec:within_topo_f1}\n\nThe cross-topology correlation between macro $F_1$ and $|\\text{bias}|$ is weak ($\\rho = -0.10$, $p = 0.45$; \\S\\ref{sec:empirical}), but decomposing by topology reveals a structured pattern. Table~\\ref{tab:within_topo_f1} reports Spearman correlations computed over 23 LLM configurations (HumAID $K{=}10$, VAST $K{=}3$, CivilComments $K{=}2$; 161 total scenarios).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Within-topology Spearman $\\rho(F_1, |\\text{bias}|)$ across 23 empirical LLM configurations $\\times$ 3 datasets. Negative $\\rho$: higher $F_1$ $\\to$ lower bias (expected). Positive $\\rho$: higher $F_1$ $\\to$ higher bias (protective attenuation removed).}\n\\label{tab:within_topo_f1}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Topology} & $n$ & $\\rho$ & $p$ \\\\\n\\midrule\nConfounding & 23 & $-0.557$ & 0.006 \\\\\nMediation & 23 & $-0.565$ & 0.005 \\\\\nExposure & 23 & $-0.531$ & 0.009 \\\\\nFront-door & 23 & $-0.568$ & 0.005 \\\\\nIV & 23 & $-0.700$ & $<$0.001 \\\\\nCollider & 23 & $+0.310$ & 0.150 \\\\\nM-bias & 23 & $+0.867$ & $<$0.001 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nFive topologies show the expected negative correlation: better annotation quality ($F_1{\\uparrow}$) reduces causal bias. IV shows the strongest effect ($\\rho = -0.70$), consistent with the Wald estimator's sensitivity to misclassification in the first stage. M-bias uniquely reverses: $\\rho = +0.87$ ($p < 0.001$). The mechanism is that misclassification attenuates the spurious M-bias path, so the naive estimator under noisy annotations is \\emph{closer} to the true causal effect; improving annotation quality (higher $F_1$) removes this protective attenuation and \\emph{increases} bias. This is consistent with the correction results (\\S\\ref{sec:correction}), where PPI++ harms M-bias ($-$88\\%) by removing the same protective noise. Collider shows a positive but non-significant trend ($\\rho = +0.31$, $p = 0.15$), consistent with Berkson bias attenuation. Per-dataset breakdowns (CivilComments $K{=}2$: $\\rho = -1.0$ for all topologies with $n{=}7$) should be interpreted with caution given the small sample and limited $F_1$ variation within the binary task.\n\n\\subsection{Confusion Matrix Estimation Robustness}\n\\label{sec:c_robustness}\n\nThe ASV framework requires the confusion matrix $C$, which in practice must be estimated from a held-out gold-labeled subset. We assess how estimation noise in $\\hat{C}$ propagates to the safe/fragile partition and ASV ranking. For each of 8 empirical confusion matrices (VAST, 4 LLMs $\\times$ 2 prompting strategies), we draw $n_{\\text{gold}} \\in \\{50, 100, 200, 500\\}$ samples from a $\\text{Multinomial}(n_{\\text{gold}}, C_{\\cdot k})$ distribution per column, compute $\\hat{C}$, and evaluate the resulting ASV ranking across 200 bootstrap replicates.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{$\\hat{C}$ estimation robustness: safe/fragile partition stability and ASV ranking correlation (Spearman $\\rho$ vs.\\ true-$C$ ranking) under multinomial bootstrap from finite gold sets. 8 empirical matrices $\\times$ 200 bootstrap replicates per $n_{\\text{gold}}$.}\n\\label{tab:c_robustness}\n\\begin{tabular}{lccc}\n\\toprule\n$n_{\\text{gold}}$ & Partition stability & $\\rho$ (median) & $\\rho$ ($q_{25}$) \\\\\n\\midrule\n50 & 50.4\\% & 0.991 & 0.789 \\\\\n100 & 82.0\\% & 1.000 & 0.991 \\\\\n200 & 85.6\\% & 1.000 & 0.991 \\\\\n500 & 88.5\\% & 1.000 & 0.991 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe ASV ranking is highly robust: median Spearman $\\rho \\geq 0.99$ even at $n_{\\text{gold}}{=}50$. The safe/fragile partition (5 safe vs.\\ 2 fragile topologies) recovers reliably from $n_{\\text{gold}} \\geq 100$ (82\\% stability), increasing to 89\\% at $n_{\\text{gold}}{=}500$. The remaining instability concentrates in source matrices with low diagonal dominance (e.g., VAST DeepSeek few-shot: $\\min C_{kk} = 0.16$), where bootstrap noise can shift borderline ASV values across the partition boundary. All 8 truth partitions match the canonical safe/fragile partition, confirming that the theoretical dichotomy holds empirically.\n\n\\subsection{Sign Reversal Determinants}\n\\label{sec:sign_determinants}\n\nWe investigate which confusion matrix features predict exposure sign reversal across the 23 empirical LLM configurations. For each matrix, we compute 10 structural features: $\\min_k C_{kk}$ (minimum diagonal), $\\overline{C_{kk}}$ (mean diagonal), $\\max_{j \\neq k} C_{jk}$ (maximum off-diagonal), $\\max_{j \\neq k} C_{jk}/C_{kk}$ (off-diagonal ratio), $\\log(\\kappa(C))$ (log condition number), mean and max column entropy, spectral gap, $\\det(C)$, and minimum singular value. Sign reversal is defined as any exposure coefficient reversing sign under misclassification.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Sign reversal rates by $K$ and best single-feature decision rule. Rule: $\\det(C) < 0.014 \\to$ sign reversal (accuracy 91.3\\%, sensitivity 85.7\\%, specificity 100\\%). An AND rule ($\\min_k C_{kk} < 0.55$ and mean entropy $> 0.40$) achieves 95.7\\% accuracy with 100\\% sensitivity.}\n\\label{tab:sign_determinants}\n\\begin{tabular}{lcc}\n\\toprule\n$K$ & $n$ & Sign reversal rate \\\\\n\\midrule\n2 & 7 & 0/7 (0\\%) \\\\",
      "numLines": 300,
      "startLine": 1170,
      "totalLines": 1538
    }
  },
  "sourceToolAssistantUUID": "f3ee547b-2475-4fe9-8696-9168ed5fd2d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 94_

```json
{
  "type": "last-prompt",
  "leafUuid": "e16b0729-447d-4592-aa84-06a13394e7c6",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 95_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Assistant

_source line 96 · 2026-05-24T06:39:33.731Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a thorough picture of the entire paper. Let me summarize my analysis.

**Part 1: Italic abuse**

After reviewing all tex files thoroughly, here are the italic issues I've found:

1. **appendix_proofs.tex:978** — `\emph{confounding topology}`: "confounding topology" is used dozens of times throughout the paper. This is not a first definition — it's just used in regular discussion. Should be de-emphasized.

2. **appendix_proofs.tex:457** — `\emph{proportional effects}`: Already defined (without italic) in method.tex line 92 ("proportional effects ($f = \lambda g$ for some scalar $\lambda$)") and line 95 ("Proportional effects ($f{=}\lambda g$)"). This is a re-emphasis in the appendix, not a first definition.
   
   Looking more closely, lines 457 and 458 are functioning as case headings within the proposition — distinguishing "proportional effects" from "general (non-proportional)" — which is standard mathematical writing. The same pattern appears at lines 465, 467, 473, and 475 where italics mark case labels. I'll keep these.

For line 978 in the ClinicalBERT case study, the emphasis on "confounding topology" is meant to highlight which taxonomy classification applies, but since the term is well-established by that point, I should remove it.

Let me check the remaining instances that were flagged, starting with the introduction section. Looking through the categories more systematically, I'm realizing that nearly all the italic uses are actually justified — proof step headers, first definitions, proposition labels, case markers, and mathematical emphasis are all standard conventions. The only genuine violation I found is that one instance of `\emph{confounding topology}` in appendix_proofs.tex:978, where the term was already established earlier in the document. Point in the paper, so that one still seems unnecessary. Let me check if any terms are italicized multiple times when they should only be emphasized on first mention — looking through the document, "sign reversal" appears in the intro but I should verify if it's consistently handled elsewhere. the term itself isn't italicized. So the formatting issues are actually quite limited. Now I'm moving on to check for formula duplication between the main text and appendix—I need to see which equations appear in both places and whether they're being repeated unnecessarily.

Looking at the main text, I've got three key equations: the confounding plim, the exposure plim, and the mediation plim. The appendix has some related equations but they're mostly in different forms—using ct/cy/q notation versus Cov/Var notation—so they're not exact duplicates. I'm also scanning through the appendix for any unlabeled inline formulas that might be repeating what's already in the main text, and so far it looks like most references are pointing back to propositions rather than restating the equations directly.

The closest overlap I'm seeing is between the mediation bias equation in the appendix and the mediation plim in the main text, but they're expressing slightly different things—one's a bias decomposition and the other's the full plim—so they're not really duplicates either.

Same story with the confounding equations: the main text uses matrix notation for intuition while the appendix gives the scalar FWL form for the proof. These are complementary formulations, not redundant ones, and the appendix properly cites back to the main text where it should.

So there's no actual formula duplication to worry about. Now I need to fix that one italic formatting issue and wrap up the report.

But let me reconsider the task more carefully—I should be looking for "italic abuse," which might include overused single-word emphasis like `\emph{all}`, `\emph{stronger}`, `\emph{causes}`. These kinds of emphases are common in academic writing when highlighting surprising points, but if they're scattered throughout, they can weaken the impact. Let me count how many times these appear... The `\emph{all}` usage appearing four times across the appendix seems justified—each instance emphasizes universal quantification in mathematical claims, whether highlighting that a property holds for all column-stochastic matrices or that a result occurred without exception across all trials. This isn't overuse; it's consistent with standard mathematical writing conventions.

So there's really just one instance of clear italic abuse to fix, no formula duplication, and the paper is otherwise clean. Let me make that correction and recompile, though I should also verify there aren't any placeholder-style italics like "in progress" scattered throughout.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e16b0729-447d-4592-aa84-06a13394e7c6",
  "isSidechain": false,
  "requestId": "req_011CbLw6TUCWU4e59jqyiypb",
  "type": "assistant",
  "uuid": "6fea77b2-becf-449b-9f51-c4a22f69e817",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VU4qrPvfFWUD9sjYat3tPe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9754,
      "cache_read_input_tokens": 105185,
      "output_tokens": 3635,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9754,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3635,
          "cache_read_input_tokens": 105185,
          "cache_creation_input_tokens": 9754,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9754
          },
          "type": "message"
        }
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

_source line 97 · 2026-05-24T06:39:36.443Z_

I've now read all the tex files. Let me compile my analysis.

**Part 1 findings:** The paper's italic usage is very clean. Most `\emph{}` uses are legitimate (proof step headings, first definitions, mathematical emphasis, case labels). I found one clear issue:

- `appendix_proofs.tex:978` — `\emph{confounding topology}` is not a first definition; the term is used dozens of times without italic throughout the paper.

**Part 2 findings:** The appendix equations use different formulations than the main text (FWL-based Cov/Var forms vs. compact summaries). No formula duplication found — the appendix derives new results and properly references main-text equations via `\ref{eq:xxx}`.

Let me fix the italic issue and compile.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6fea77b2-becf-449b-9f51-c4a22f69e817",
  "isSidechain": false,
  "requestId": "req_011CbLw6TUCWU4e59jqyiypb",
  "type": "assistant",
  "uuid": "694ba336-c797-4582-9ce4-a51f67ce91ef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VU4qrPvfFWUD9sjYat3tPe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9754,
      "cache_read_input_tokens": 105185,
      "output_tokens": 3635,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9754,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3635,
          "cache_read_input_tokens": 105185,
          "cache_creation_input_tokens": 9754,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9754
          },
          "type": "message"
        }
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

_source line 98 · 2026-05-24T06:39:38.608Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01RfMbci5UG11Q6pWpjWsbVo`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
  "old_string": "Our taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.",
  "new_string": "Our taxonomy identifies this as a confounding topology: the annotated variable enters as a confounder between treatment and outcome."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "694ba336-c797-4582-9ce4-a51f67ce91ef",
  "isSidechain": false,
  "requestId": "req_011CbLw6TUCWU4e59jqyiypb",
  "type": "assistant",
  "uuid": "2e4b88db-ab1e-4ea9-a3a7-4168cfba9d89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VU4qrPvfFWUD9sjYat3tPe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9754,
      "cache_read_input_tokens": 105185,
      "output_tokens": 3635,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9754,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3635,
          "cache_read_input_tokens": 105185,
          "cache_creation_input_tokens": 9754,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9754
          },
          "type": "message"
        }
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

_source line 99 · 2026-05-24T06:39:38.636Z_

<details><summary>↩ Tool result · `toolu_01RfMbci5UG11Q6pWpjWsbVo`</summary>

```text
The file /home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2e4b88db-ab1e-4ea9-a3a7-4168cfba9d89",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "4c18acef-8004-4b26-9868-dd99c9a9090a",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper/appendix_proofs.tex",
    "oldString": "Our taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.",
    "newString": "Our taxonomy identifies this as a confounding topology: the annotated variable enters as a confounder between treatment and outcome.",
    "originalFile": null,
    "structuredPatch": [
      {
        "oldStart": 975,
        "oldLines": 7,
        "newStart": 975,
        "newLines": 7,
        "lines": [
          " \\label{app:case_study}",
          " ",
          " To demonstrate the framework's end-to-end utility, we apply it retrospectively to \\citet{lee_wood_doughty2024}, who use ClinicalBERT to classify patient smoking status ($K{=}4$: never, past, current, unknown) from clinical notes and control for this predicted confounder when estimating the causal effect of echocardiography on mortality in 4{,}735 MIMIC-III sepsis patients.",
          "-Our taxonomy identifies this as a \\emph{confounding topology}: the annotated variable enters as a confounder between treatment and outcome.",
          "+Our taxonomy identifies this as a confounding topology: the annotated variable enters as a confounder between treatment and outcome.",
          " Three conclusions follow directly.",
          " First, the zero sign-flip guarantee for confounding (Table~\\ref{tab:taxonomy}) ensures that the estimated protective effect (OR~$= 0.89$) cannot reverse direction due to annotation error---a reassurance unavailable without topology-specific analysis.",
          " Second, the FWL invariance result implies that any correction reducing to $C^{-1}$ applied to the dummy-coded confounder achieves exactly 0\\% bias reduction for the treatment coefficient; naive plug-in is provably futile here."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "2e4b88db-ab1e-4ea9-a3a7-4168cfba9d89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 100 · 2026-05-24T06:39:40.806Z_

Now let me compile.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4c18acef-8004-4b26-9868-dd99c9a9090a",
  "isSidechain": false,
  "requestId": "req_011CbLwCftVQ63jxj4R7AU5g",
  "type": "assistant",
  "uuid": "b70307d7-263b-49e2-b461-3cdedd869309",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XgZGNz271fKQRCSenz9Mp1",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3708,
      "cache_read_input_tokens": 114939,
      "output_tokens": 155,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3708,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 155,
          "cache_read_input_tokens": 114939,
          "cache_creation_input_tokens": 3708,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3708
          },
          "type": "message"
        }
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

_source line 101 · 2026-05-24T06:39:42.201Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01RRjt65MgjVvmkbkVYQVF3F`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper && latexmk -pdf -interaction=nonstopmode main.tex 2>&1 | tail -20",
  "description": "Compile LaTeX paper",
  "timeout": 120000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b70307d7-263b-49e2-b461-3cdedd869309",
  "isSidechain": false,
  "requestId": "req_011CbLwCftVQ63jxj4R7AU5g",
  "type": "assistant",
  "uuid": "1c15b184-b157-470c-8099-0def04edd537",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XgZGNz271fKQRCSenz9Mp1",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3708,
      "cache_read_input_tokens": 114939,
      "output_tokens": 155,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3708,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 155,
          "cache_read_input_tokens": 114939,
          "cache_creation_input_tokens": 3708,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3708
          },
          "type": "message"
        }
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

_source line 102 · 2026-05-24T06:39:44.876Z_

<details><summary>↩ Tool result · `toolu_01RRjt65MgjVvmkbkVYQVF3F`</summary>

```text
exmf-dist/fonts/type1/public/amsfonts/cm/cmti10.pfb>&lt;/usr/share/texlive/texmf-d
ist/fonts/type1/public/amsfonts/cm/cmti9.pfb>&lt;/usr/share/texlive/texmf-dist/fon
ts/type1/public/amsfonts/cm/cmtt10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/typ
e1/public/amsfonts/symbols/msam10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type
1/public/amsfonts/symbols/msbm10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1
/urw/helvetic/uhvb8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/zapfdin
g/uzdr.pfb>
Output written on main.pdf (36 pages, 973555 bytes).
Transcript written on main.log.
Latexmk: Getting log file 'main.log'
Latexmk: Examining 'main.fls'
Latexmk: Examining 'main.log'
Latexmk: Found input bbl file 'main.bbl'
Latexmk: Log file says output to 'main.pdf'
Latexmk: Using bibtex to make bibliography file(s).
  ===Source file 'main.bbl' for 'pdflatex'
Latexmk: Found bibliography file(s):
  ./references.bib
Latexmk: All targets (main.pdf) are up-to-date
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1c15b184-b157-470c-8099-0def04edd537",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "4ff81447-f04f-4e0b-92dc-b482246a10c1",
  "toolUseResult": {
    "stdout": "exmf-dist/fonts/type1/public/amsfonts/cm/cmti10.pfb>&lt;/usr/share/texlive/texmf-d\nist/fonts/type1/public/amsfonts/cm/cmti9.pfb>&lt;/usr/share/texlive/texmf-dist/fon\nts/type1/public/amsfonts/cm/cmtt10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/typ\ne1/public/amsfonts/symbols/msam10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type\n1/public/amsfonts/symbols/msbm10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1\n/urw/helvetic/uhvb8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/zapfdin\ng/uzdr.pfb>\nOutput written on main.pdf (36 pages, 973555 bytes).\nTranscript written on main.log.\nLatexmk: Getting log file 'main.log'\nLatexmk: Examining 'main.fls'\nLatexmk: Examining 'main.log'\nLatexmk: Found input bbl file 'main.bbl'\nLatexmk: Log file says output to 'main.pdf'\nLatexmk: Using bibtex to make bibliography file(s).\n  ===Source file 'main.bbl' for 'pdflatex'\nLatexmk: Found bibliography file(s):\n  ./references.bib\nLatexmk: All targets (main.pdf) are up-to-date",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "1c15b184-b157-470c-8099-0def04edd537",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 103_

```json
{
  "type": "last-prompt",
  "leafUuid": "4ff81447-f04f-4e0b-92dc-b482246a10c1",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 104_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Tool call

_source line 105 · 2026-05-24T06:39:49.115Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01EQps5PdaRnRQGABdukdXXH`</summary>

```json
{
  "command": "grep -c \"undefined\" main.log && grep \"LaTeX Warning.*undefined\" main.log | head -5; echo \"---\"; grep \"^!\" main.log | head -5; echo \"---page count---\"; grep \"Output written\" main.log",
  "description": "Check for undefined references and errors"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4ff81447-f04f-4e0b-92dc-b482246a10c1",
  "isSidechain": false,
  "requestId": "req_011CbLwD8CXXN2wd5yNwDVSS",
  "type": "assistant",
  "uuid": "9fa46502-ac4f-41e7-8719-fa18d2baba05",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FqESJXAokpvQ1xgB5rbpRH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 602,
      "cache_read_input_tokens": 118647,
      "output_tokens": 164,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 602,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 164,
          "cache_read_input_tokens": 118647,
          "cache_creation_input_tokens": 602,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 602
          },
          "type": "message"
        }
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

_source line 106 · 2026-05-24T06:39:49.183Z_

<details><summary>↩ Tool result · `toolu_01EQps5PdaRnRQGABdukdXXH`</summary>

```text
0
---
---page count---
Output written on main.pdf (36 pages, 973555 bytes).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9fa46502-ac4f-41e7-8719-fa18d2baba05",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "66115c85-0050-4282-9956-f6aabe82f053",
  "toolUseResult": {
    "stdout": "0\n---\n---page count---\nOutput written on main.pdf (36 pages, 973555 bytes).",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "9fa46502-ac4f-41e7-8719-fa18d2baba05",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 107 · 2026-05-24T06:39:52.598Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01TD7fYfDmnEdHybDJXrKkYT`</summary>

```json
{
  "command": "grep -i \"undefined\" main.log | head -5; echo \"===\"; grep \"^!\" main.log | head -5",
  "description": "Check for undefined references and errors in log"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "66115c85-0050-4282-9956-f6aabe82f053",
  "isSidechain": false,
  "requestId": "req_011CbLwDSaKWKTSHV8mMheSD",
  "type": "assistant",
  "uuid": "d096612e-8750-4350-8c4d-46d737b4605b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U8maz18CGCGstPpfm853Go",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 168,
      "cache_read_input_tokens": 119249,
      "output_tokens": 138,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 168,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 138,
          "cache_read_input_tokens": 119249,
          "cache_creation_input_tokens": 168,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 168
          },
          "type": "message"
        }
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

_source line 108 · 2026-05-24T06:39:52.655Z_

<details><summary>↩ Tool result · `toolu_01TD7fYfDmnEdHybDJXrKkYT`</summary>

```text
===
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d096612e-8750-4350-8c4d-46d737b4605b",
  "isSidechain": false,
  "promptId": "d001b298-5ba9-4ea6-a0a8-f0c0dc557d54",
  "type": "user",
  "uuid": "5be23351-a431-4144-85d0-05979d10b31d",
  "toolUseResult": {
    "stdout": "===",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "d096612e-8750-4350-8c4d-46d737b4605b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 109 · 2026-05-24T06:40:10.375Z_

编译成功。0 errors, 0 undefined references, 36 pages（正文 8 页 + 附录）。

---

## 汇报

### 1. 斜体修复清单

| 文件:行号 | 修改 | 原因 |
|---|---|---|
| `appendix_proofs.tex:978` | `\emph{confounding topology}` → `confounding topology` | "confounding topology" 在全文已出现数十次（method.tex、experiments.tex、附录多处），不是首次定义，属于重复强调 |

其余所有 `\emph{}` 和 `\textit{}` 均为合法用途：
- 证明步骤标题（Step 1:, Derivation., Sign analysis. 等）— 标准数学写作
- 首次定义术语（starred-node, protective, immune, conditional indirect effect, component-wise diagonal dominance 等）
- 命题标签（(a), (b), (c)）
- 数学强调（all, constant, causes 等）— 强调普遍性/反直觉结果
- 枚举配置标签（Diagonal-dominant, Moderate noise 等）
- 关键结果强调（structure, vanishes, worsen 等）— 对比/反直觉语境

### 2. 公式重复清理清单

**无重复公式。** 附录中的方程使用与正文不同的数学形式：
- `eq:plim_conf`（附录）用 FWL 标量形式 vs `eq:confounding`（正文）用矩阵形式
- `eq:med_bias`（附录）用 Cov/Var 形式 vs `eq:mediation`（正文）用 λ(C) 参数化形式
- 附录在需要引用正文公式时正确使用了 `\ref{eq:xxx}`（如 line 445: "Substituting back into~\eqref{eq:mediation}"）

### 3. 编译结果

- 0 errors
- 0 undefined references
- 36 pages（正文 8 页以内）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5be23351-a431-4144-85d0-05979d10b31d",
  "isSidechain": false,
  "requestId": "req_011CbLwDhTH2gk4Cj7mQS17M",
  "type": "assistant",
  "uuid": "b6f8d839-7226-4091-a416-f4cf545ccccd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/docs/paper",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017SJP1tKhu7T8XRdJv3DyyZ",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 117,
      "cache_read_input_tokens": 119417,
      "output_tokens": 581,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 117,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 581,
          "cache_read_input_tokens": 119417,
          "cache_creation_input_tokens": 117,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 117
          },
          "type": "message"
        }
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

_source line 110_

```json
{
  "type": "last-prompt",
  "leafUuid": "b6f8d839-7226-4091-a416-f4cf545ccccd",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

### Runtime record

_source line 111_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix italic overuse and deduplicate appendix formulas",
  "sessionId": "e79c5c6a-c505-464a-beed-9ce58a792bcc"
}
```

---

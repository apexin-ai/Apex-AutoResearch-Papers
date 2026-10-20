# Research conversation: <project_context> # 项目: ec_hte_llm_annotation ## 运行环境 - 服务器名: local-cpu - SSH 账户: ubuntu（调用 ssh_execute / submit_trainin

**When Debiasing Hurts: An Exact Bias Identity for LLM-Annotated Treatment Effects (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 23
- **Recorded user turns:** 1
- **Tool calls:** 4
- **Original source:** `logs/chats/exported-trajectories/account-2/057f7a49-0f58-488c-b692-f259d0d8706d.jsonl`
- **Structured JSON:** [`4b8d951f7fadd657315e.json`](../../sessions/4b/4b8d951f7fadd657315e.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-21T18:45:53.789Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-21T18:45:53.789Z",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "content": "&lt;project_context>\n# 项目: ec_hte_llm_annotation\n\n## 运行环境\n- 服务器名: local-cpu\n- SSH 账户: ubuntu（调用 ssh_execute / submit_training_job 时传入 account=\"ubuntu\"）\n- SSH 连接命令: ssh local-cpu  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /home/ubuntu/ec_hte_llm_annotation\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n## 任务：准备 C1 Multi-LLM Validation 结果整合模板\n\n项目路径：`/home/ubuntu/ec_hte_llm_annotation/`\n论文路径：`/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/`\n\n### 背景\n\n4 个开源模型（Llama-3.1-8B, Qwen2.5-7B, Mistral-7B, Gemma-2-9B）在 balanced-Z TweetEval 数据上的标注实验正在跑。需要提前准备论文整合模板，GPU 结果出来后直接填数字。\n\n### 任务\n\n创建 `artifacts/c1_integration_template.tex`，包含：\n\n#### 1. experiments.tex 的补充段落框架\n\n在现有 Semi-Real Validation 之后，添加一个 Multi-LLM Validation subsection：\n\n```latex\n\\subsection{Multi-LLM Validation}\n\\label{sec:multi_llm}\n\nTo validate EC-HTE beyond a single annotator model, we apply four open-source LLMs---Llama-3.1-8B-Instruct, Qwen2.5-7B-Instruct, Mistral-7B-Instruct-v0.3, and Gemma-2-9B-IT---to the TweetEval sentiment task with a balanced subgroup definition ($P(Z{=}1) \\approx [TBD]$).\nTable~\\ref{tab:multi_llm} summarizes the per-model misclassification profiles and correction performance.\n\n[TBD: 1-2 sentences on key finding — e.g., EC-HTE improves over global in X/4 models where cond(M̂) < threshold]\n\n[TBD: 1 sentence on which models satisfy the Prop 2 diagnostic condition]\n\n[TBD: 1 sentence connecting to applicability conditions from Section~\\ref{sec:budget}]\n```\n\n#### 2. 主文 Table 模板\n\n```latex\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & $P(Z{=}1)$ & $\\kappa(\\hat{M})$ & eff.\\ $n$ & RMSE\\textsubscript{naive} & RMSE\\textsubscript{global} & RMSE\\textsubscript{EC-HTE} \\\\\n\\midrule\nLlama-3.1-8B & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nQwen2.5-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nMistral-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nGemma-2-9B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Multi-LLM validation on TweetEval ($N{=}500$, balanced $Z$). [TBD: complete caption]}\n\\label{tab:multi_llm}\n\\end{table}\n```\n\n#### 3. Appendix 详细表格模板\n\nPer-model per-subgroup confusion matrix 和详细指标：\n\n```latex\n\\section{Multi-LLM Detailed Results}\n\\label{app:multi_llm}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\begin{tabular}{llcccccc}\n\\toprule\nModel & $Z$ & $n$ & Accuracy & FPR & FNR & $\\pi_s$ & $\\kappa(\\hat{M}_s)$ \\\\\n\\midrule\n\\multirow{2}{*}{Llama-3.1-8B} & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n[... repeat for other 3 models ...]\n\\bottomrule\n\\end{tabular}\n\\caption{Per-subgroup misclassification profiles for four open-source LLMs on TweetEval sentiment ($Z{=}0$: negative, $Z{=}1$: neutral+positive).}\n\\label{tab:multi_llm_detail}\n\\end{table*}\n```\n\n### 注意\n\n- 先 Read `experiments.tex` 和 `appendix.tex` 了解现有结构和风格\n- 模板应与现有论文风格一致（字体大小、表格格式、caption 风格）\n- 占位符用 `[TBD]` 标注\n- 创建目录 `artifacts/` 如果不存在\n- 输出到 `/home/ubuntu/ec_hte_llm_annotation/artifacts/c1_integration_template.tex`\n\n### 验证\n\n确认文件语法正确（无 LaTeX 编译错误的明显问题）。"
}
````

---

### Runtime record

_source line 2 · 2026-05-21T18:45:53.792Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-21T18:45:53.792Z",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d"
}
```

---

## Round 1

21 recorded events

### User

_source line 3 · 2026-05-21T18:45:53.825Z_

&lt;project_context>
# 项目: ec_hte_llm_annotation

## 运行环境
- 服务器名: local-cpu
- SSH 账户: ubuntu（调用 ssh_execute / submit_training_job 时传入 account="ubuntu"）
- SSH 连接命令: ssh local-cpu  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /home/ubuntu/ec_hte_llm_annotation


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
## 任务：准备 C1 Multi-LLM Validation 结果整合模板

项目路径：`/home/ubuntu/ec_hte_llm_annotation/`
论文路径：`/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/`

### 背景

4 个开源模型（Llama-3.1-8B, Qwen2.5-7B, Mistral-7B, Gemma-2-9B）在 balanced-Z TweetEval 数据上的标注实验正在跑。需要提前准备论文整合模板，GPU 结果出来后直接填数字。

### 任务

创建 `artifacts/c1_integration_template.tex`，包含：

#### 1. experiments.tex 的补充段落框架

在现有 Semi-Real Validation 之后，添加一个 Multi-LLM Validation subsection：

```latex
\subsection{Multi-LLM Validation}
\label{sec:multi_llm}

To validate EC-HTE beyond a single annotator model, we apply four open-source LLMs---Llama-3.1-8B-Instruct, Qwen2.5-7B-Instruct, Mistral-7B-Instruct-v0.3, and Gemma-2-9B-IT---to the TweetEval sentiment task with a balanced subgroup definition ($P(Z{=}1) \approx [TBD]$).
Table~\ref{tab:multi_llm} summarizes the per-model misclassification profiles and correction performance.

[TBD: 1-2 sentences on key finding — e.g., EC-HTE improves over global in X/4 models where cond(M̂) < threshold]

[TBD: 1 sentence on which models satisfy the Prop 2 diagnostic condition]

[TBD: 1 sentence connecting to applicability conditions from Section~\ref{sec:budget}]
```

#### 2. 主文 Table 模板

```latex
\begin{table}[t]
\centering
\small
\begin{tabular}{lcccccc}
\toprule
Model & $P(Z{=}1)$ & $\kappa(\hat{M})$ & eff.\ $n$ & RMSE\textsubscript{naive} & RMSE\textsubscript{global} & RMSE\textsubscript{EC-HTE} \\
\midrule
Llama-3.1-8B & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\
Qwen2.5-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\
Mistral-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\
Gemma-2-9B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\
\bottomrule
\end{tabular}
\caption{Multi-LLM validation on TweetEval ($N{=}500$, balanced $Z$). [TBD: complete caption]}
\label{tab:multi_llm}
\end{table}
```

#### 3. Appendix 详细表格模板

Per-model per-subgroup confusion matrix 和详细指标：

```latex
\section{Multi-LLM Detailed Results}
\label{app:multi_llm}

\begin{table*}[t]
\centering
\small
\begin{tabular}{llcccccc}
\toprule
Model & $Z$ & $n$ & Accuracy & FPR & FNR & $\pi_s$ & $\kappa(\hat{M}_s)$ \\
\midrule
\multirow{2}{*}{Llama-3.1-8B} & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\
 & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\
\midrule
[... repeat for other 3 models ...]
\bottomrule
\end{tabular}
\caption{Per-subgroup misclassification profiles for four open-source LLMs on TweetEval sentiment ($Z{=}0$: negative, $Z{=}1$: neutral+positive).}
\label{tab:multi_llm_detail}
\end{table*}
```

### 注意

- 先 Read `experiments.tex` 和 `appendix.tex` 了解现有结构和风格
- 模板应与现有论文风格一致（字体大小、表格格式、caption 风格）
- 占位符用 `[TBD]` 标注
- 创建目录 `artifacts/` 如果不存在
- 输出到 `/home/ubuntu/ec_hte_llm_annotation/artifacts/c1_integration_template.tex`

### 验证

确认文件语法正确（无 LaTeX 编译错误的明显问题）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "500ceecd-d23e-42ba-9539-45d70198290e",
  "type": "user",
  "uuid": "13b7504c-fbb5-4fa6-9f8d-909b3d185c9b",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-21T18:45:53.825Z_

```json
{
  "parentUuid": "13b7504c-fbb5-4fa6-9f8d-909b3d185c9b",
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
  "uuid": "cb9ae07d-133e-4d5c-b306-0ae3b721bf74",
  "timestamp": "2026-05-21T18:45:53.825Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-21T18:45:53.825Z_

```json
{
  "parentUuid": "cb9ae07d-133e-4d5c-b306-0ae3b721bf74",
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
  "uuid": "ca3cd9ce-8234-4b50-bc37-65e0d47dc43f",
  "timestamp": "2026-05-21T18:45:53.825Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-21T18:45:53.825Z_

```json
{
  "parentUuid": "ca3cd9ce-8234-4b50-bc37-65e0d47dc43f",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "fb813658-17bb-41d8-847b-afeedcf33280",
  "timestamp": "2026-05-21T18:45:53.825Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
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
  "aiTitle": "Prepare Multi-LLM validation paper template",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d"
}
```

---

### Assistant

_source line 8 · 2026-05-21T18:45:57.091Z_

<details><summary>Logged reasoning block</summary>

```text
Let me read the existing paper files to understand the style and structure before creating the template.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fb813658-17bb-41d8-847b-afeedcf33280",
  "isSidechain": false,
  "requestId": "req_011CbGDA33EA5xUM2Z6KW8ca",
  "type": "assistant",
  "uuid": "83651156-4fbd-47d2-a3b0-62de689390d0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TCBb6AsTBAbtGNgFMjoTLP",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12988,
      "cache_read_input_tokens": 11841,
      "output_tokens": 285,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12988,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 285,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12988,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12988
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-21T18:45:57.663Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NZ1zDLprFzucmrDvNJy5eE`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "83651156-4fbd-47d2-a3b0-62de689390d0",
  "isSidechain": false,
  "requestId": "req_011CbGDA33EA5xUM2Z6KW8ca",
  "type": "assistant",
  "uuid": "7dea650b-c023-4ac1-b001-70637655d66b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TCBb6AsTBAbtGNgFMjoTLP",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12988,
      "cache_read_input_tokens": 11841,
      "output_tokens": 285,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12988,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 285,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12988,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12988
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-21T18:45:57.679Z_

<details><summary>↩ Tool result · `toolu_01NZ1zDLprFzucmrDvNJy5eE`</summary>

```text
1	\section{Experiments}
2	
3	\subsection{Setup}
4	
5	We evaluate on synthetic and semi-synthetic data generating processes (DGPs); full specifications appear in Appendix~\ref{app:dgp}.
6	The synthetic DGP generates $N{=}5{,}000$ observations from a randomized trial with $K \in \{2, 4\}$ subgroups, controlled CATE heterogeneity $\Delta\tau$, and subgroup-specific symmetric misclassification rates with heterogeneity $\Delta\pi$.
7	Expert labels ($n_{\text{expert}} \in \{50, \ldots, 2000\}$) are a simple random sample with true $Z$ observed; each configuration is repeated for 100 Monte Carlo runs.
8	The semi-synthetic DGP samples $N{=}5{,}000$ tweets from TweetEval sentiment~\cite{barbieri2020tweeteval}, defining $K{=}4$ subgroups by crossing hashtag presence and text length (unbalanced: 39\%/38\%/12\%/11\%), with misclassification rates $\pi \in \{0.05, 0.10, 0.15, 0.25\}$ reflecting empirical evidence that text features degrade LLM accuracy~\cite{ashwin2025bias}.
9	
10	We compare: (1) \textit{Naive} (no correction), (2) \textit{Global} (pooled confusion matrix), (3) \textit{Stratified MLE} (per-subgroup MLE without pooling), (4) \textit{HB EC-HTE} (our method), (5) \textit{PPCI}~\cite{sui2026ppci}, and (6) \textit{EC-HTE+PPCI}.
11	For CausalForest~\cite{wager2018causal}, we compare naive, global, and EC-HTE variants.
12	Our Global baseline is equivalent to PPI/DSL~\cite{angelopoulos2023ppi,egami2024dsl} applied with a pooled (homogeneous) error rate; Stratified MLE corresponds to per-subgroup DSL without hierarchical shrinkage.
13	EC-HTE extends this by borrowing strength across subgroups via hierarchical Bayesian estimation.
14	Primary metrics are $|\text{bias}|$, RMSE, and 95\% CI coverage, averaged across subgroups and 100 MC runs.
15	Real-data validation on hate speech detection confirms $\Delta\pi = 0.117$ across text-feature subgroups (Appendix~\ref{app:hatespeech}).
16	The heterogeneity pattern persists across six OpenAI models spanning three generations (Appendix~\ref{app:multilm}).
17	EC-HTE maintains $\geq$94.5\% coverage under up to 50\% subgroup misspecification noise (Appendix~\ref{app:robustness}).
18	When empirical asymmetric confusion matrices from the GPT-4.1 pilot are used directly, a subgroup with FNR~$\approx 0.5$ causes EC-HTE to underperform global correction at all budgets (Appendix~\ref{app:semireal}).
19	
20	\subsection{Bias Mechanism Verification}
21	\label{sec:bias_mechanism}
22	
23	The bias decomposition identity (Theorem~\ref{thm:bias_identity}) predicts that global correction introduces bias proportional to $\Delta\pi \times \Delta\tau$ at the subgroup level.
24	We verify this identity empirically across 520 configurations spanning $K \in \{2,4\}$, two misclassification regimes, and six expert budget levels.
25	Regressing observed subgroup bias on the predicted $\Delta\pi \times \Delta\tau$ product yields $R^2 = 0.994$ for $K{=}2$ and $R^2 = 0.974$ for $K{=}4$; the residual variance reflects MC sampling noise rather than model misspecification, since Theorem~\ref{thm:bias_identity} is an exact identity at the population level ($R^2 \geq 0.976$ even at $P(Z{=}1) = 0.1$; Appendix~\ref{app:classimbalance}).
26	In 50\% of configurations (260/520, excluding $\Delta_c{=}0$ rows where bias is zero by construction), global correction produces larger absolute bias than the naive estimator.
27	The damage concentrates in low-$\pi$ subgroups: among subgroups where $\pi_s < \bar{\pi}$, global correction increases bias in 84.6\% of cases.
28	Maximum observed amplification reaches 2.86$\times$ (K=2) and 2.41$\times$ (K=4) relative to the naive estimator.
29	Figure~\ref{fig:heatmap} visualizes the $\Delta\pi \times \Delta\tau$ amplification surface across the parameter grid.
30	
31	\begin{figure*}[t]
32	\centering
33	\includegraphics[width=\textwidth]{figures/fig2_heatmap.pdf}
34	\caption{Bias amplification under global correction across the $\Delta\pi \times \Delta\tau$ parameter grid ($K{=}2$). (a) Low-error subgroup: global correction always helps (ratio $< 1$). (b) High-error subgroup: when $\Delta\pi > 0.12$ (dashed line), global correction \emph{increases} bias relative to the naive estimator (hatched region), with amplification reaching 2.86$\times$.}
35	\label{fig:heatmap}
36	\end{figure*}
37	
38	\subsection{EC-HTE Evaluation}
39	\label{sec:ec_hte_eval}
40	
41	Table~\ref{tab:main_results} presents the main results across representative configurations.
42	In the synthetic DGP with $K{=}2$ subgroups and extreme misclassification heterogeneity, HB EC-HTE reduces $|\text{bias}|$ from 0.059 (global) to 0.011 (a 5.4$\times$ reduction) while maintaining nominal coverage (0.95) and comparable RMSE (0.093 vs.\ 0.099).
43	The advantage persists at $K{=}4$: EC-HTE achieves $|\text{bias}|{=}0.009$ versus 0.056 for global (6.2$\times$ reduction), though with a small RMSE penalty (0.127 vs.\ 0.125).
44	Under moderate heterogeneity ($K{=}2$), methods converge: EC-HTE and global achieve comparable bias ($p > 0.05$; Table~\ref{tab:main_supp}).
45	In the semi-synthetic TweetEval experiment ($N{=}5{,}000$, $K{=}4$), global correction achieves the lowest $|\text{bias}|$ (0.023), while EC-HTE attains 0.027 with higher RMSE (0.225 vs.\ 0.124), consistent with moderate $\Delta\pi{=}0.20$ and unbalanced subgroup sizes (Table~\ref{tab:main_supp}).
46	
47	\paragraph{CausalForest K-dependence.}
48	When the downstream estimator is a CausalForest~\cite{wager2018causal}, the bias mechanism operates with amplified magnitude.
49	At $K{=}4$/extreme/$n{=}500$, EC-HTE Forest reduces $|\text{bias}|$ from 0.191 (global) to 0.040, a 4.8$\times$ improvement with dramatically better coverage (0.91 vs.\ 0.58).
50	The debiasing-hurts phenomenon intensifies: global correction amplifies naive bias by up to 5.9$\times$ in the worst subgroup, because the forest's sensitivity to covariate noise magnifies the effect of label errors.
51	At $K{=}4$/$n{=}100$, EC-HTE Forest RMSE reaches 1.43 (3.5$\times$ naive), underscoring the budget guidelines in Section~\ref{sec:budget}.
52	
53	\begin{table}[t]
54	\centering
55	\caption{Main results under extreme misclassification heterogeneity. $|\text{Bias}|$ and RMSE averaged over subgroups, $z$-levels, and 100 MC runs. Bold marks lowest $|\text{bias}|$ per block. $^\dagger$RMSE exceeds Global, reflecting stratification variance cost. Additional configurations (moderate heterogeneity, semi-synthetic TweetEval) in Table~\ref{tab:main_supp}. MC standard errors: Appendix~\ref{app:mcse}.}
56	\label{tab:main_results}
57	\small
58	\begin{tabular}{ll ccc}
59	\toprule
60	Configuration & Method & $|\text{Bias}|$ & RMSE & Cov. \\
61	\midrule
62	\multirow{4}{*}{\shortstack[l]{DIM\\$K{=}2$, $n{=}250$}}
63	 & Naive & 0.058 & 0.090 & 0.82 \\
64	 & Global & 0.059 & 0.099 & 0.87 \\
65	 & Strat.\ MLE & 0.012 & 0.094 & 0.95 \\
66	 & HB EC-HTE & \textbf{0.011} & 0.093 & 0.95 \\
67	\midrule
68	\multirow{4}{*}{\shortstack[l]{DIM\\$K{=}4$, $n{=}500$}}
69	 & Naive & 0.062 & 0.113 & 0.88 \\
70	 & Global & 0.056 & 0.125 & 0.91 \\
71	 & Strat.\ MLE & 0.010 & 0.127$^\dagger$ & 0.95 \\
72	 & HB EC-HTE & \textbf{0.009} & 0.127$^\dagger$ & 0.95 \\
73	\midrule
74	\multirow{3}{*}{\shortstack[l]{CausalForest\\$K{=}4$, $n{=}500$}}
75	 & Naive & 0.208 & 0.231 & 0.44 \\
76	 & Global & 0.191 & 0.244 & 0.58 \\
77	 & EC-HTE Forest & \textbf{0.040} & 0.224 & 0.91 \\
78	\bottomrule
79	\end{tabular}
80	\end{table}
81	
82	\subsection{Diagnostic Criterion}
83	\label{sec:diagnostic}
84	
85	Proposition~\ref{prop:debiasing_hurts} provides a $\Delta\tau$-free diagnostic: global correction increases bias in subgroup $s$ if and only if $|\delta_s| / ((1-2\bar{\pi}) \cdot \pi_s) > 1$, where $\delta_s = \pi_s - \bar{\pi}$.
86	This condition depends only on per-subgroup misclassification rates estimable from a pilot sample, breaking the circular dependency that would arise if the diagnostic required CATE estimates.
87	Since the Proposition~\ref{prop:debiasing_hurts} score is a deterministic function of per-subgroup misclassification rates, a threshold classifier achieves AUC = 0.87 at the subgroup level for predicting whether global correction increases bias relative to the naive estimator.
88	At the setting level, the condition achieves AUC = 0.89 (vs.\ 0.47 for the $\Delta\pi \times \Delta\tau$ product), because it identifies settings where \emph{any} subgroup is harmed.
89	Figure~\ref{fig:roc} (Appendix) shows the ROC curve.
90	
91	\paragraph{Recommended workflow.}
92	\begin{enumerate}[nosep,leftmargin=*]
93	\item Collect $n \geq 25K / P(Z_{\text{minority}})$ stratified expert labels (e.g., $n \geq 500$ for $K{=}4$, $P(Z{=}1){=}0.2$); compute per-subgroup $\pi_s$ and $\bar{\pi}$.
94	\item Verify (a)~$n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$ and (b)~worst-subgroup $\max(\text{FPR}, \text{FNR}) < 0.5$; if either fails, use global correction.
95	\item If any subgroup satisfies $|\delta_s| / ((1-2\bar{\pi}) \cdot \pi_s) > 1$ (Proposition~\ref{prop:debiasing_hurts}), apply EC-HTE; apply PPCI regardless for outcome error (Section~\ref{sec:ppci}).
96	\end{enumerate}
97	
98	\subsection{Expert Budget Analysis}
99	\label{sec:budget}
100	
101	The crossover point at which EC-HTE achieves lower RMSE than global correction is $n_{\text{expert}} = 250$ for $K{=}2$/extreme and $n_{\text{expert}} = 1000$ for $K{=}4$/extreme (Figure~\ref{fig:budget} in the Appendix).
102	Under moderate heterogeneity ($K{=}2$), EC-HTE never achieves lower RMSE than global at any budget.
103	HB partial pooling improves over stratified MLE in 21 of 24 configurations, with the two estimators converging by $n_{\text{expert}} \geq 1000$.
104	
105	\subsection{PPCI Complementarity and Estimator Robustness}
106	\label{sec:ppci}
107	
108	EC-HTE composes with PPCI~\cite{sui2026ppci} for settings where both covariate misclassification and outcome model error are present: EC-HTE+PPCI reduces $|\text{bias}|$ from 0.179 to 0.007 ($z{=}0$, DGP~C), and the corrected pseudo-outcomes are compatible with other CATE estimators (R-learner bias reduction: 89\%; Appendix~\ref{app:ppci},~\ref{app:rlearner}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7dea650b-c023-4ac1-b001-70637655d66b",
  "isSidechain": false,
  "promptId": "500ceecd-d23e-42ba-9539-45d70198290e",
  "type": "user",
  "uuid": "95b04d5a-14e5-4197-93eb-f7ccc639cd8b",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\n\\subsection{Setup}\n\nWe evaluate on synthetic and semi-synthetic data generating processes (DGPs); full specifications appear in Appendix~\\ref{app:dgp}.\nThe synthetic DGP generates $N{=}5{,}000$ observations from a randomized trial with $K \\in \\{2, 4\\}$ subgroups, controlled CATE heterogeneity $\\Delta\\tau$, and subgroup-specific symmetric misclassification rates with heterogeneity $\\Delta\\pi$.\nExpert labels ($n_{\\text{expert}} \\in \\{50, \\ldots, 2000\\}$) are a simple random sample with true $Z$ observed; each configuration is repeated for 100 Monte Carlo runs.\nThe semi-synthetic DGP samples $N{=}5{,}000$ tweets from TweetEval sentiment~\\cite{barbieri2020tweeteval}, defining $K{=}4$ subgroups by crossing hashtag presence and text length (unbalanced: 39\\%/38\\%/12\\%/11\\%), with misclassification rates $\\pi \\in \\{0.05, 0.10, 0.15, 0.25\\}$ reflecting empirical evidence that text features degrade LLM accuracy~\\cite{ashwin2025bias}.\n\nWe compare: (1) \\textit{Naive} (no correction), (2) \\textit{Global} (pooled confusion matrix), (3) \\textit{Stratified MLE} (per-subgroup MLE without pooling), (4) \\textit{HB EC-HTE} (our method), (5) \\textit{PPCI}~\\cite{sui2026ppci}, and (6) \\textit{EC-HTE+PPCI}.\nFor CausalForest~\\cite{wager2018causal}, we compare naive, global, and EC-HTE variants.\nOur Global baseline is equivalent to PPI/DSL~\\cite{angelopoulos2023ppi,egami2024dsl} applied with a pooled (homogeneous) error rate; Stratified MLE corresponds to per-subgroup DSL without hierarchical shrinkage.\nEC-HTE extends this by borrowing strength across subgroups via hierarchical Bayesian estimation.\nPrimary metrics are $|\\text{bias}|$, RMSE, and 95\\% CI coverage, averaged across subgroups and 100 MC runs.\nReal-data validation on hate speech detection confirms $\\Delta\\pi = 0.117$ across text-feature subgroups (Appendix~\\ref{app:hatespeech}).\nThe heterogeneity pattern persists across six OpenAI models spanning three generations (Appendix~\\ref{app:multilm}).\nEC-HTE maintains $\\geq$94.5\\% coverage under up to 50\\% subgroup misspecification noise (Appendix~\\ref{app:robustness}).\nWhen empirical asymmetric confusion matrices from the GPT-4.1 pilot are used directly, a subgroup with FNR~$\\approx 0.5$ causes EC-HTE to underperform global correction at all budgets (Appendix~\\ref{app:semireal}).\n\n\\subsection{Bias Mechanism Verification}\n\\label{sec:bias_mechanism}\n\nThe bias decomposition identity (Theorem~\\ref{thm:bias_identity}) predicts that global correction introduces bias proportional to $\\Delta\\pi \\times \\Delta\\tau$ at the subgroup level.\nWe verify this identity empirically across 520 configurations spanning $K \\in \\{2,4\\}$, two misclassification regimes, and six expert budget levels.\nRegressing observed subgroup bias on the predicted $\\Delta\\pi \\times \\Delta\\tau$ product yields $R^2 = 0.994$ for $K{=}2$ and $R^2 = 0.974$ for $K{=}4$; the residual variance reflects MC sampling noise rather than model misspecification, since Theorem~\\ref{thm:bias_identity} is an exact identity at the population level ($R^2 \\geq 0.976$ even at $P(Z{=}1) = 0.1$; Appendix~\\ref{app:classimbalance}).\nIn 50\\% of configurations (260/520, excluding $\\Delta_c{=}0$ rows where bias is zero by construction), global correction produces larger absolute bias than the naive estimator.\nThe damage concentrates in low-$\\pi$ subgroups: among subgroups where $\\pi_s < \\bar{\\pi}$, global correction increases bias in 84.6\\% of cases.\nMaximum observed amplification reaches 2.86$\\times$ (K=2) and 2.41$\\times$ (K=4) relative to the naive estimator.\nFigure~\\ref{fig:heatmap} visualizes the $\\Delta\\pi \\times \\Delta\\tau$ amplification surface across the parameter grid.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig2_heatmap.pdf}\n\\caption{Bias amplification under global correction across the $\\Delta\\pi \\times \\Delta\\tau$ parameter grid ($K{=}2$). (a) Low-error subgroup: global correction always helps (ratio $< 1$). (b) High-error subgroup: when $\\Delta\\pi > 0.12$ (dashed line), global correction \\emph{increases} bias relative to the naive estimator (hatched region), with amplification reaching 2.86$\\times$.}\n\\label{fig:heatmap}\n\\end{figure*}\n\n\\subsection{EC-HTE Evaluation}\n\\label{sec:ec_hte_eval}\n\nTable~\\ref{tab:main_results} presents the main results across representative configurations.\nIn the synthetic DGP with $K{=}2$ subgroups and extreme misclassification heterogeneity, HB EC-HTE reduces $|\\text{bias}|$ from 0.059 (global) to 0.011 (a 5.4$\\times$ reduction) while maintaining nominal coverage (0.95) and comparable RMSE (0.093 vs.\\ 0.099).\nThe advantage persists at $K{=}4$: EC-HTE achieves $|\\text{bias}|{=}0.009$ versus 0.056 for global (6.2$\\times$ reduction), though with a small RMSE penalty (0.127 vs.\\ 0.125).\nUnder moderate heterogeneity ($K{=}2$), methods converge: EC-HTE and global achieve comparable bias ($p > 0.05$; Table~\\ref{tab:main_supp}).\nIn the semi-synthetic TweetEval experiment ($N{=}5{,}000$, $K{=}4$), global correction achieves the lowest $|\\text{bias}|$ (0.023), while EC-HTE attains 0.027 with higher RMSE (0.225 vs.\\ 0.124), consistent with moderate $\\Delta\\pi{=}0.20$ and unbalanced subgroup sizes (Table~\\ref{tab:main_supp}).\n\n\\paragraph{CausalForest K-dependence.}\nWhen the downstream estimator is a CausalForest~\\cite{wager2018causal}, the bias mechanism operates with amplified magnitude.\nAt $K{=}4$/extreme/$n{=}500$, EC-HTE Forest reduces $|\\text{bias}|$ from 0.191 (global) to 0.040, a 4.8$\\times$ improvement with dramatically better coverage (0.91 vs.\\ 0.58).\nThe debiasing-hurts phenomenon intensifies: global correction amplifies naive bias by up to 5.9$\\times$ in the worst subgroup, because the forest's sensitivity to covariate noise magnifies the effect of label errors.\nAt $K{=}4$/$n{=}100$, EC-HTE Forest RMSE reaches 1.43 (3.5$\\times$ naive), underscoring the budget guidelines in Section~\\ref{sec:budget}.\n\n\\begin{table}[t]\n\\centering\n\\caption{Main results under extreme misclassification heterogeneity. $|\\text{Bias}|$ and RMSE averaged over subgroups, $z$-levels, and 100 MC runs. Bold marks lowest $|\\text{bias}|$ per block. $^\\dagger$RMSE exceeds Global, reflecting stratification variance cost. Additional configurations (moderate heterogeneity, semi-synthetic TweetEval) in Table~\\ref{tab:main_supp}. MC standard errors: Appendix~\\ref{app:mcse}.}\n\\label{tab:main_results}\n\\small\n\\begin{tabular}{ll ccc}\n\\toprule\nConfiguration & Method & $|\\text{Bias}|$ & RMSE & Cov. \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{DIM\\\\$K{=}2$, $n{=}250$}}\n & Naive & 0.058 & 0.090 & 0.82 \\\\\n & Global & 0.059 & 0.099 & 0.87 \\\\\n & Strat.\\ MLE & 0.012 & 0.094 & 0.95 \\\\\n & HB EC-HTE & \\textbf{0.011} & 0.093 & 0.95 \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{DIM\\\\$K{=}4$, $n{=}500$}}\n & Naive & 0.062 & 0.113 & 0.88 \\\\\n & Global & 0.056 & 0.125 & 0.91 \\\\\n & Strat.\\ MLE & 0.010 & 0.127$^\\dagger$ & 0.95 \\\\\n & HB EC-HTE & \\textbf{0.009} & 0.127$^\\dagger$ & 0.95 \\\\\n\\midrule\n\\multirow{3}{*}{\\shortstack[l]{CausalForest\\\\$K{=}4$, $n{=}500$}}\n & Naive & 0.208 & 0.231 & 0.44 \\\\\n & Global & 0.191 & 0.244 & 0.58 \\\\\n & EC-HTE Forest & \\textbf{0.040} & 0.224 & 0.91 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Diagnostic Criterion}\n\\label{sec:diagnostic}\n\nProposition~\\ref{prop:debiasing_hurts} provides a $\\Delta\\tau$-free diagnostic: global correction increases bias in subgroup $s$ if and only if $|\\delta_s| / ((1-2\\bar{\\pi}) \\cdot \\pi_s) > 1$, where $\\delta_s = \\pi_s - \\bar{\\pi}$.\nThis condition depends only on per-subgroup misclassification rates estimable from a pilot sample, breaking the circular dependency that would arise if the diagnostic required CATE estimates.\nSince the Proposition~\\ref{prop:debiasing_hurts} score is a deterministic function of per-subgroup misclassification rates, a threshold classifier achieves AUC = 0.87 at the subgroup level for predicting whether global correction increases bias relative to the naive estimator.\nAt the setting level, the condition achieves AUC = 0.89 (vs.\\ 0.47 for the $\\Delta\\pi \\times \\Delta\\tau$ product), because it identifies settings where \\emph{any} subgroup is harmed.\nFigure~\\ref{fig:roc} (Appendix) shows the ROC curve.\n\n\\paragraph{Recommended workflow.}\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item Collect $n \\geq 25K / P(Z_{\\text{minority}})$ stratified expert labels (e.g., $n \\geq 500$ for $K{=}4$, $P(Z{=}1){=}0.2$); compute per-subgroup $\\pi_s$ and $\\bar{\\pi}$.\n\\item Verify (a)~$n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$ and (b)~worst-subgroup $\\max(\\text{FPR}, \\text{FNR}) < 0.5$; if either fails, use global correction.\n\\item If any subgroup satisfies $|\\delta_s| / ((1-2\\bar{\\pi}) \\cdot \\pi_s) > 1$ (Proposition~\\ref{prop:debiasing_hurts}), apply EC-HTE; apply PPCI regardless for outcome error (Section~\\ref{sec:ppci}).\n\\end{enumerate}\n\n\\subsection{Expert Budget Analysis}\n\\label{sec:budget}\n\nThe crossover point at which EC-HTE achieves lower RMSE than global correction is $n_{\\text{expert}} = 250$ for $K{=}2$/extreme and $n_{\\text{expert}} = 1000$ for $K{=}4$/extreme (Figure~\\ref{fig:budget} in the Appendix).\nUnder moderate heterogeneity ($K{=}2$), EC-HTE never achieves lower RMSE than global at any budget.\nHB partial pooling improves over stratified MLE in 21 of 24 configurations, with the two estimators converging by $n_{\\text{expert}} \\geq 1000$.\n\n\\subsection{PPCI Complementarity and Estimator Robustness}\n\\label{sec:ppci}\n\nEC-HTE composes with PPCI~\\cite{sui2026ppci} for settings where both covariate misclassification and outcome model error are present: EC-HTE+PPCI reduces $|\\text{bias}|$ from 0.179 to 0.007 ($z{=}0$, DGP~C), and the corrected pseudo-outcomes are compatible with other CATE estimators (R-learner bias reduction: 89\\%; Appendix~\\ref{app:ppci},~\\ref{app:rlearner}).",
      "numLines": 108,
      "startLine": 1,
      "totalLines": 108
    }
  },
  "sourceToolAssistantUUID": "7dea650b-c023-4ac1-b001-70637655d66b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-21T18:45:58.155Z_

<details open><summary>🔧 Tool call — Read · `toolu_012HyNZL4upbhACTzfUgFwae`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "95b04d5a-14e5-4197-93eb-f7ccc639cd8b",
  "isSidechain": false,
  "requestId": "req_011CbGDA33EA5xUM2Z6KW8ca",
  "type": "assistant",
  "uuid": "823daf34-e330-417c-8162-43e1d11ad59e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TCBb6AsTBAbtGNgFMjoTLP",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12988,
      "cache_read_input_tokens": 11841,
      "output_tokens": 285,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12988,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 285,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12988,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12988
          },
          "type": "message"
        }
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

_source line 12 · 2026-05-21T18:45:58.674Z_

<details><summary>↩ Tool result · `toolu_012HyNZL4upbhACTzfUgFwae`</summary>

```text
1	\section{EC-HTE Procedure}
2	\label{app:algorithm}
3	
4	\begin{algorithm}[t]
5	\caption{EC-HTE: Error-Corrected Heterogeneous Treatment Effects}
6	\label{alg:echte}
7	\begin{algorithmic}[1]
8	\Require Observations $\{(Y_i, W_i, \hat{Z}_i, X_i)\}_{i=1}^N$; expert labels $\{Z_j^*\}_{j=1}^{n_{\text{expert}}}$; subgroup map $S: \mathcal{X} \to \{1,\ldots,K\}$
9	\Ensure Corrected CATE estimates $\hat{\tau}(z)$ with variance-adjusted CIs
10	\Statex
11	\State \textbf{Step 1: Estimate per-subgroup confusion matrices (HB)}
12	\For{$s = 1, \ldots, K$}
13	    \State $C_s[j,\cdot] \sim \mathrm{Dir}(\alpha_0 \cdot \mathbf{e}_j)$, \; $\alpha_0 \sim \mathrm{Gamma}(3,1)$
14	    \State Gibbs sampler (4 chains, 4000 iter) on $\{(\hat{Z}_j, Z_j^*) : S_j = s\}$
15	    \State $\hat{C}_s \gets$ posterior mean; verify $\hat{R} < 1.01$
16	\EndFor
17	\Statex
18	\State \textbf{Step 2: Correct observed outcome moments}
19	\For{$s = 1, \ldots, K$}
20	    \If{$\kappa(\hat{C}_s) > 100$} $\hat{C}_s \gets \bar{C}$ \Comment{singularity guard}
21	    \EndIf
22	    \State $\tilde{\boldsymbol{\mu}}_s \gets \hat{C}_s^{-1} \hat{\boldsymbol{\mu}}_s$
23	\EndFor
24	\Statex
25	\State \textbf{Step 3: CausalForestDML with variance-adjusted SEs}
26	\State Train CausalForest (honest splitting) on corrected labels
27	\State $\mathrm{se}_{\mathrm{adj},i} \gets \sqrt{\mathrm{diag}(\hat{C}_{S_i}^{-1}\, \mathrm{diag}(\mathrm{se}_i^2)\, \hat{C}_{S_i}^{-\top})}$
28	\State \Return $\hat{\tau}(z)$ with 95\% CIs from $\mathrm{se}_{\mathrm{adj}}$
29	\end{algorithmic}
30	\end{algorithm}
31	
32	\section{Full Proof of Theorem~\ref{thm:bias_identity}}
33	\label{app:derivation}
34	
35	\paragraph{Setup.}
36	Under assumptions (A1)--(A4), the observed CATE in subgroup $s$ at effect-modifier level $z$ is
37	\begin{equation}
38	\tau_{\text{obs}}(z, s) = \sum_{z'} M_s[z, z'] \cdot \tau(z'),
39	\end{equation}
40	where $M_s[z, z'] = P(Z{=}z' \mid \hat{Z}{=}z, S{=}s)$ is the mixing matrix.
41	Under (A2)--(A3), $M_s = \bigl[\begin{smallmatrix} 1-\pi_s & \pi_s \\ \pi_s & 1-\pi_s \end{smallmatrix}\bigr]$.
42	
43	\paragraph{Global correction.}
44	The pooled mixing matrix is $M_{\text{global}} = \sum_s w_s M_s = \bigl[\begin{smallmatrix} 1-\bar{\pi} & \bar{\pi} \\ \bar{\pi} & 1-\bar{\pi} \end{smallmatrix}\bigr]$, with $\bar{\pi} = \sum_s w_s \pi_s$.
45	
46	Global correction applies $M_{\text{global}}^{-1}$ to $\tau_{\text{obs}}(\cdot, s)$:
47	\begin{equation}
48	\hat{\tau}_{\text{global}}(z, s) = [M_{\text{global}}^{-1} M_s \cdot \boldsymbol{\tau}]_z,
49	\end{equation}
50	where $\boldsymbol{\tau} = [\tau(0), \tau(1)]^\top$.
51	
52	\paragraph{Bias computation.}
53	The bias is $\hat{\tau}_{\text{global}}(z, s) - \tau(z) = [(M_{\text{global}}^{-1} M_s - I) \boldsymbol{\tau}]_z$.
54	
55	Direct computation gives:
56	\begin{equation}
57	M_{\text{global}}^{-1} = \frac{1}{1 - 2\bar{\pi}} \begin{bmatrix} 1-\bar{\pi} & -\bar{\pi} \\ -\bar{\pi} & 1-\bar{\pi} \end{bmatrix}.
58	\end{equation}
59	Multiplying by $M_s$:
60	\begin{equation}
61	\resizebox{.88\columnwidth}{!}{$\displaystyle
62	M_{\text{global}}^{-1} M_s = \frac{1}{1-2\bar{\pi}} \begin{bmatrix} (1{-}\bar{\pi})(1{-}\pi_s) - \bar{\pi}\pi_s & (1{-}\bar{\pi})\pi_s - \bar{\pi}(1{-}\pi_s) \\ -\bar{\pi}(1{-}\pi_s) + (1{-}\bar{\pi})\pi_s & -\bar{\pi}\pi_s + (1{-}\bar{\pi})(1{-}\pi_s) \end{bmatrix}.
63	$}
64	\end{equation}
65	
66	Define $\delta_s = \pi_s - \bar{\pi}$. The $(1,1)$ entry simplifies:
67	{\small
68	\begin{align}
69	(1{-}\bar{\pi})(1{-}\pi_s) - \bar{\pi}\pi_s &= 1 - \bar{\pi} - \pi_s + 2\bar{\pi}\pi_s \nonumber\\
70	&= (1 - 2\bar{\pi}) + (\bar{\pi} - \pi_s) + 2\bar{\pi}\pi_s \nonumber\\
71	&= (1 - 2\bar{\pi}) - \delta_s.
72	\end{align}
73	}
74	
75	More directly, substituting $\pi_s = \bar{\pi} + \delta_s$:
76	\begin{equation}
77	M_{\text{global}}^{-1} M_s - I = \frac{\delta_s}{1-2\bar{\pi}} \begin{bmatrix} -1 & 1 \\ 1 & -1 \end{bmatrix}.
78	\end{equation}
79	
80	To verify: the $(1,1)$ entry of $M_{\text{global}}^{-1} M_s$ is
81	{\small
82	\begin{align}
83	&\frac{(1{-}\bar{\pi})(1{-}\bar{\pi}{-}\delta_s) - \bar{\pi}(\bar{\pi}{+}\delta_s)}{1-2\bar{\pi}} \nonumber\\
84	&= \frac{(1{-}\bar{\pi})^2 - (1{-}\bar{\pi})\delta_s - \bar{\pi}^2 - \bar{\pi}\delta_s}{1-2\bar{\pi}} \nonumber\\
85	&= \frac{1 - 2\bar{\pi} - \delta_s}{1-2\bar{\pi}} = 1 - \frac{\delta_s}{1-2\bar{\pi}}.
86	\end{align}
87	}
88	
89	Applying $(M_{\text{global}}^{-1} M_s - I)$ to $\boldsymbol{\tau}$:
90	{\small
91	\begin{align}
92	\text{bias}(z{=}0, s) &= \tfrac{\delta_s}{1-2\bar{\pi}}(-\tau(0) + \tau(1)) = +\tfrac{\delta_s \cdot \Delta\tau}{1-2\bar{\pi}}, \\
93	\text{bias}(z{=}1, s) &= \tfrac{\delta_s}{1-2\bar{\pi}}(\tau(0) - \tau(1)) = -\tfrac{\delta_s \cdot \Delta\tau}{1-2\bar{\pi}},
94	\end{align}
95	}
96	where $\Delta\tau = \tau(1) - \tau(0)$. \qed
97	
98	\section{Multi-class Extension and Proof}
99	\label{app:multiclass}
100	
101	\begin{corollary}[Multi-class Extension]
102	\label{cor:multiclass}
103	For $K > 2$ subgroups with $J$ effect-modifier levels, the subgroup bias of global correction generalizes to
104	\begin{equation}
105	\mathrm{bias}_{\mathrm{global}}(z, s) = \sum_{j=1}^{J} \bigl(\bar{\pi}_j - \pi_{s,j}\bigr) \cdot \bigl(\tau(j) - \bar{\tau}\bigr) \cdot g(\bar{\pi}),
106	\label{eq:multiclass}
107	\end{equation}
108	where $g(\bar{\pi})$ collects the matrix-inversion amplification terms.\footnote{For $J=3$ with symmetric misclassification (off-diagonal errors uniform), $g(\bar{\pi}) = 1/(1 - 3\bar{\pi}/2)$, generalizing the $J{=}2$ factor $1/(1-2\bar{\pi})$. In general, $g(\bar{\pi}) = 1/(1 - J\bar{\pi}/(J-1))$.}
109	The essential structure, $\sum_s w_s (\bar{\pi}_j - \pi_{s,j}) = 0$, ensures that bias redistributes across subgroups rather than vanishing in aggregate.
110	\end{corollary}
111	
112	\paragraph{Proof.}
113	For $K > 2$ subgroups with $J$ effect-modifier levels, the subgroup-specific mixing matrix $M_s$ is $J \times J$ with entries $M_s[j, j'] = P(Z{=}j' \mid \hat{Z}{=}j, S{=}s)$.
114	The global mixing matrix is $M_{\text{global}} = \sum_s w_s M_s$.
115	
116	The bias of global correction in subgroup $s$ at level $z$ is:
117	\begin{equation}
118	\text{bias}_{\text{global}}(z, s) = [(M_{\text{global}}^{-1} M_s - I) \boldsymbol{\tau}]_z.
119	\end{equation}
120	
121	Write $M_s = M_{\text{global}} + \Delta_s$ where $\Delta_s = M_s - M_{\text{global}}$ satisfies $\sum_s w_s \Delta_s = 0$.
122	Then $M_{\text{global}}^{-1} M_s = I + M_{\text{global}}^{-1} \Delta_s$, so:
123	\begin{equation}
124	\text{bias}_{\text{global}}(z, s) = [M_{\text{global}}^{-1} \Delta_s \cdot \boldsymbol{\tau}]_z.
125	\end{equation}
126	
127	For symmetric misclassification with per-class error rates $\pi_{s,j}$ and pooled rates $\bar{\pi}_j$, the entries of $\Delta_s$ have the form $\Delta_s[j,j'] = (\bar{\pi}_j - \pi_{s,j}) \cdot h(j, j')$ for a function $h$ determined by the off-diagonal redistribution pattern.
128	Expanding the matrix-vector product and collecting terms yields:
129	\begin{equation}
130	\text{bias}_{\text{global}}(z, s) = \sum_{j=1}^{J} (\bar{\pi}_j - \pi_{s,j}) \cdot (\tau(j) - \bar{\tau}) \cdot g(\bar{\pi}),
131	\end{equation}
132	where $g(\bar{\pi})$ collects the matrix-inversion amplification terms and $\bar{\tau} = \sum_j P(Z{=}j) \tau(j)$.
133	
134	The essential structure $\sum_s w_s (\bar{\pi}_j - \pi_{s,j}) = 0$ ensures that the weighted bias across subgroups sums to zero: global correction redistributes bias rather than creating or eliminating it in aggregate. \qed
135	
136	\section{Proof of Proposition~\ref{prop:debiasing_hurts}}
137	\label{app:debiasing_hurts}
138	
139	The naive estimator has bias $\tau_{\text{obs}}(z,s) - \tau(z)$.
140	Under (A2)--(A3), $\tau_{\text{obs}}(0,s) = (1-\pi_s)\tau(0) + \pi_s\tau(1)$, so $\text{bias}_{\text{naive}}(0,s) = \pi_s \cdot \Delta\tau$.
141	
142	Global correction produces larger absolute bias when $|\text{bias}_{\text{global}}(0,s)| > |\text{bias}_{\text{naive}}(0,s)|$:
143	\begin{equation}
144	\frac{|\delta_s| \cdot |\Delta\tau|}{|1-2\bar{\pi}|} > \pi_s \cdot |\Delta\tau|.
145	\end{equation}
146	Since $\Delta\tau \neq 0$ (otherwise both biases are zero), dividing through gives:
147	\begin{equation}
148	\frac{|\delta_s|}{(1-2\bar{\pi}) \cdot \pi_s} > 1,
149	\end{equation}
150	where we use $1-2\bar{\pi} > 0$ from (A4).
151	
152	For high-error subgroups ($\pi_s > \bar{\pi}$, so $\delta_s > 0$): the condition becomes $(\pi_s - \bar{\pi}) / ((1-2\bar{\pi})\pi_s) > 1$, which simplifies to $\pi_s(1 - 1 + 2\bar{\pi}) > \bar{\pi}$, i.e., $2\bar{\pi}\pi_s > \bar{\pi}$, i.e., $\pi_s > 0.5$.
153	This is excluded by (A4), so global correction always reduces bias in high-error subgroups.
154	
155	For low-error subgroups ($\pi_s < \bar{\pi}$, so $\delta_s < 0$): the condition becomes $(\bar{\pi} - \pi_s) / ((1-2\bar{\pi})\pi_s) > 1$, which gives $\pi_s < \bar{\pi} / (1 - 2\bar{\pi} + 1) = \bar{\pi} / (2(1-\bar{\pi}))$.
156	When $\bar{\pi} = 0.15$, any subgroup with $\pi_s < 0.088$ experiences increased bias from global correction. \qed
157	
158	\section{Semi-Synthetic Data Generating Process}
159	\label{app:dgp}
160	
161	\paragraph{Synthetic DGP (Sections~\ref{sec:bias_mechanism}--\ref{sec:budget}).}
162	We generate $N = 5000$ observations.
163	Each observation belongs to one of $K \in \{2, 4\}$ subgroups $S \in \{1, \ldots, K\}$ with equal weights $w_s = 1/K$.
164	The binary effect modifier $Z \in \{0, 1\}$ is drawn with $P(Z{=}1) = 0.5$.
165	Treatment assignment is $T \sim \text{Bernoulli}(0.5)$, independent of $Z$ and $S$.
166	
167	The outcome is generated as:
168	\begin{equation}
169	Y = \tau(Z) \cdot T + \varepsilon, \quad \varepsilon \sim \mathcal{N}(0, 1),
170	\end{equation}
171	where the CATE function is $\tau(z) = \bar{\tau} + \Delta\tau \cdot (z - 0.5)$ with $\bar{\tau} = 0.5$.
172	The CATE heterogeneity $\Delta\tau \in \{0, 0.2, 0.5, 1.0\}$ controls the strength of treatment effect variation across levels of $Z$.
173	
174	Misclassification is symmetric: $\hat{Z} \neq Z$ with probability $\pi_s$ depending on subgroup.
175	For $K{=}2$: $\pi_1 = \bar{\pi} - \Delta_c/2$, $\pi_2 = \bar{\pi} + \Delta_c/2$, with $\bar{\pi} \in \{0.1, 0.2\}$ and $\Delta_c \in \{0, 0.05, 0.1, 0.15\}$.
176	For $K{=}4$, extreme regime: $\pi \in \{0.05, 0.10, 0.15, 0.25\}$; moderate regime: $\pi \in \{0.08, 0.12, 0.16, 0.20\}$.
177	
178	Expert labels are drawn as a simple random sample of size $n_{\text{expert}} \in \{50, 100, 250, 500, 1000, 2000\}$ from the full dataset, with true $Z$ observed for these observations.
179	
180	\paragraph{Semi-synthetic DGP (Section~\ref{sec:ec_hte_eval}).}
181	We sample $N = 5000$ tweets from the TweetEval sentiment corpus ($N_{\text{pool}} = 57{,}899$).
182	Subgroups are defined by crossing \texttt{has\_hashtag} $\times$ \texttt{text\_length\_bin} (short/medium/long), yielding $K = 4$ subgroups with empirical sizes: $S_0 \approx 38\%$, $S_1 \approx 38\%$, $S_2 \approx 12\%$, $S_3 \approx 12\%$.
183	Misclassification rates in the extreme regime are $\pi_{S_0} = 0.05$, $\pi_{S_1} = 0.10$, $\pi_{S_2} = 0.15$, $\pi_{S_3} = 0.25$, reflecting empirical evidence that hashtag-heavy text degrades LLM classifier accuracy.
184	The outcome DGP follows the same structure as the synthetic case, with CATE injected onto the real text-derived subgroup structure.
185	
186	\paragraph{PPCI DGPs (Section~\ref{sec:ppci}).}
187	Four DGPs isolate error types: (A) covariate error only ($\sigma_{\text{outcome}} = 0$), (B) outcome error only ($\sigma_{\text{outcome}} = 0.5$), (C) both errors ($\sigma_{\text{outcome}} = 0.5$), (D) no error ($\sigma_{\text{outcome}} = 0$).
188	Outcome-side error is additive Gaussian noise on $Y$.
189	
190	\section{Extended Related Work}
191	\label{app:related}
192	
193	\paragraph{Measurement error details.}
194	\citet{fuller1987measurement} establish the foundational theory showing that naive regression with mismeasured covariates yields attenuated coefficient estimates.
195	\citet{carroll2006measurement} extend this to nonlinear models.
196	\citet{gustafson2003measurement} develops Bayesian treatments modeling measurement jointly with outcomes.
197	\citet{hu2008nonparametric} provide nonparametric identification using repeated measurements or instruments.
198	
199	\paragraph{Annotation model extensions.}
200	Beyond the foundational \citet{dawid1979maximum} model, \citet{passonneau2014benefits} incorporate item difficulty, \citet{hovy2013learning} learn annotator competence, and \citet{paun2018comparing} introduce hierarchical priors sharing information across annotators with varying expertise.
201	
202	\paragraph{PPI extensions and text-as-data methods.}
203	\citet{zrnic2024cross} extend PPI via cross-prediction; their active inference framework~\citep{zrnic2024active} achieves $>$80\% expert budget savings through adaptive allocation, complementary to our fixed-budget analysis.
204	\citet{grimmer2022text} and \citet{audinet2025benchmarking} provide broader methodological guidance for text-as-data pipelines without specific correction for causal heterogeneity.
205	
206	\paragraph{Treatment vs.\ effect-modifier misclassification.}
207	\citet{imai2010causal} study treatment misclassification where errors change which arm a unit is assigned to, requiring instrumental variables or partial identification because the fundamental treated-vs-control contrast is corrupted.
208	Our problem preserves the treatment contrast ($T$ is observed correctly) but corrupts the heterogeneity structure ($\hat{Z} \neq Z$).
209	The ATE remains identified; only conditional effects are biased, which makes exact correction through confusion matrix inversion feasible.
210	
211	\section{MCMC Convergence Diagnostics}
212	\label{app:mcmc}
213	
214	Table~\ref{tab:mcmc} reports convergence diagnostics for the hierarchical Bayesian confusion matrix estimator across all experimental configurations.
215	All runs use 4 chains with 4000 iterations (2000 warmup) and a $\text{Gamma}(3, 1)$ hyperprior on the Dirichlet concentration $\alpha_0$.
216	
217	\begin{table}[h]
218	\centering
219	\small
220	\begin{tabular}{lcc}
221	\toprule
222	Diagnostic & Threshold & Achieved \\
223	\midrule
224	$\hat{R}$ (max across all params) & $< 1.01$ & $< 1.0034$ \\
225	ESS (min across all params) & $> 845$ & $> 1618$ \\
226	Divergent transitions & $= 0$ & $0$ \\
227	Singularity guard triggers & --- & extreme/$n{=}50$ only \\
228	\bottomrule
229	\end{tabular}
230	\caption{MCMC convergence diagnostics for the hierarchical Bayesian estimator. All configurations satisfy convergence criteria with substantial margin.}
231	\label{tab:mcmc}
232	\end{table}
233	
234	\paragraph{Hyperprior sensitivity.}
235	Scaling the $\text{Gamma}(3, 1)$ hyperprior by factors of $0.5\times$ to $2\times$ produces $<$1\% RMSE variation for $K{=}2$ and $\sim$4--5\% for $K{=}4$.
236	Coverage remains invariant across the sensitivity range.
237	These results confirm that the hierarchical estimator is robust to prior specification within a reasonable range.
238	
239	\section{Diagnostic ROC Curves}
240	\label{app:roc}
241	
242	\begin{figure}[t]
243	\centering
244	\includegraphics[width=\columnwidth]{figures/fig4_roc.png}
245	\caption{ROC curves for the $\Delta\tau$-free diagnostic (Proposition~\ref{prop:debiasing_hurts}): $|\delta_s|/((1{-}2\bar\pi)\cdot\pi_s)>1$. (A)~Setting-level ROC (AUC $= 0.89$), compared with the $|\Delta\pi \times \Delta\tau|$ product (AUC $= 0.89$) and $\mathrm{CV}(\pi_s)$ (AUC $= 0.97$). (B)~Subgroup-level ROC: the $\Delta\pi$-only condition (AUC $= 0.87$) substantially outperforms the $|\Delta\pi \times \Delta\tau|$ product (AUC $= 0.73$). The $\Delta\tau$-free diagnostic depends only on estimable misclassification rates, breaking the circular dependency that would arise if CATE heterogeneity were required.}
246	\label{fig:roc}
247	\end{figure}
248	
249	\section{Expert Budget Crossover Curves}
250	\label{app:budget}
251	
252	\begin{figure*}[t]
253	\centering
254	\includegraphics[width=\textwidth]{figures/fig3_budget.pdf}
255	\caption{RMSE vs.\ expert budget ($n_{\text{expert}}$) across four regime$\times K$ combinations. Dashed vertical lines mark crossover points where EC-HTE achieves lower RMSE than global correction: $n{=}250$ ($K{=}2$, extreme), $n{=}1000$ ($K{=}4$, extreme). Under moderate heterogeneity ($K{=}2$), global correction dominates at all budgets. Shaded bands show $\pm 1$ SD across subgroups within each configuration.}
256	\label{fig:budget}
257	\end{figure*}
258	
259	\section{Asymmetric Misclassification Extension}
260	\label{app:asymmetric}
261	
262	Assumption~(A2) imposes symmetric misclassification ($\text{FPR}_s = \text{FNR}_s = \pi_s$), which simplifies the bias decomposition but is not necessary for it.
263	Real LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.
264	
265	\paragraph{General bias formula.}
266	For asymmetric confusion matrices $C_s = \bigl(\begin{smallmatrix} 1{-}\text{FPR}_s & \text{FPR}_s \\ \text{FNR}_s & 1{-}\text{FNR}_s \end{smallmatrix}\bigr)$, define the mixing matrix $M_s$ via Bayesian inversion and the residual matrix $B_s = M_{\text{global}}^{-1} M_s - I$.
267	Since both $M_s$ and $M_{\text{global}}$ are row-stochastic, $B_s \mathbf{1} = \mathbf{0}$.
268	Decomposing $\boldsymbol{\tau} = \tau(0)\mathbf{1} + \Delta\tau \, \mathbf{e}_1$ gives:
269	\begin{equation}
270	\text{bias}(z, s) = \Delta\tau \cdot [B_s]_{z,1},
271	\end{equation}
272	where $[B_s]_{z,1}$ depends only on $\{\text{FPR}_k, \text{FNR}_k, w_k\}$, not on $\Delta\tau$.
273	Under~(A2), this reduces to $\delta_s \Delta\tau / (1 - 2\bar{\pi})$ (Theorem~\ref{thm:bias_identity}).
274	
275	\paragraph{Empirical validation.}
276	We test three asymmetric configurations ($K{=}2$, $n_{\text{expert}}{=}250$, 100 MC runs each): \emph{Cross} (FPR/FNR = 0.10/0.20 vs.\ 0.25/0.10), \emph{Co-directional} (0.05/0.15 vs.\ 0.20/0.30), and \emph{Extreme} (0.03/0.25 vs.\ 0.30/0.05).
277	Regressing analytic predictions on MC bias yields $R^2 = 0.991$ across all configurations, confirming the product structure under asymmetry.
278	Table~\ref{tab:asymmetric} reports correction performance averaged over subgroups, $z$-levels, and $\Delta\tau \in \{0.1, \ldots, 0.5\}$.
279	EC-HTE reduces $|\text{bias}|$ from 0.025 (global) to 0.006, a $4\times$ improvement, with lower RMSE (0.033 vs.\ 0.040) and substantially better coverage (0.90 vs.\ 0.78).
280	
281	\begin{table}[t]
282	\centering
283	\caption{Asymmetric misclassification results ($K{=}2$, $n_{\text{expert}}{=}250$, 100 MC runs). Values averaged over subgroups, $z$-levels, and $\Delta\tau$.}
284	\label{tab:asymmetric}
285	\small
286	\begin{tabular}{l ccc}
287	\toprule
288	Method & $|\text{Bias}| \downarrow$ & RMSE $\downarrow$ & Coverage $\uparrow$ \\
289	\midrule
290	Naive & 0.047 & 0.053 & 0.48 \\
291	Global & 0.025 & 0.040 & 0.78 \\
292	HB EC-HTE & \textbf{0.006} & \textbf{0.033} & \textbf{0.90} \\
293	\bottomrule
294	\end{tabular}
295	\end{table}
296	
297	\section{Supplementary Main Results}
298	\label{app:main_supp}
299	
300	\begin{table}[t]
301	\centering
302	\caption{Additional configurations from the main experiment. $|\text{Bias}|$ and RMSE averaged over subgroups, $z$-levels, and 100 MC runs. $^\dagger$RMSE exceeds Global.}
303	\label{tab:main_supp}
304	\small
305	\begin{tabular}{ll ccc}
306	\toprule
307	Configuration & Method & $|\text{Bias}|$ & RMSE & Cov. \\
308	\midrule
309	\multirow{4}{*}{\shortstack[l]{Synthetic DIM\\$K{=}2$, moderate, $n{=}250$}}
310	 & Naive & 0.018 & 0.064 & 0.95 \\
311	 & Global & 0.009 & 0.074 & 0.96 \\
312	 & Strat.\ MLE & \textbf{0.005} & 0.075$^\dagger$ & 0.97 \\
313	 & HB EC-HTE & \textbf{0.005} & 0.075$^\dagger$ & 0.97 \\
314	\midrule
315	\multirow{4}{*}{\shortstack[l]{Semi-synthetic\\TweetEval, extreme, $n{=}250$}}
316	 & Naive & 0.027 & 0.103 & 0.93 \\
317	 & Global & \textbf{0.023} & 0.124 & 0.92 \\
318	 & Strat.\ MLE & 0.032 & 0.248$^\dagger$ & 0.91 \\
319	 & HB EC-HTE & 0.027 & 0.225$^\dagger$ & 0.91 \\
320	\bottomrule
321	\end{tabular}
322	\end{table}
323	
324	\section{PPCI Complementarity Results}
325	\label{app:ppci}
326	
327	\begin{table*}[t]
328	\centering
329	\caption{PPCI complementarity experiment ($K{=}2$, extreme, $n_{\text{expert}}{=}250$). DGP~A: covariate error only; B: outcome error only ($\sigma{=}0.5$); C: both errors; D: no error. Values are $|\text{bias}|$ and RMSE averaged over two subgroups. $^\star$EC-HTE+PPCI achieves near-zero bias when both error types are present.}
330	\label{tab:ppci}
331	\small
332	\begin{tabular}{ll cccc}
333	\toprule
334	DGP & Method & $|\text{Bias}|_{z=0}$ & $|\text{Bias}|_{z=1}$ & RMSE$_{z=0}$ & RMSE$_{z=1}$ \\
335	\midrule
336	\multirow{5}{*}{A: Covariate}
337	 & Naive & 0.053 & 0.063 & 0.087 & 0.093 \\
338	 & Global & 0.063 & 0.055 & 0.101 & 0.102 \\
339	 & EC-HTE & 0.017 & \textbf{0.013} & 0.097 & 0.108 \\
340	 & PPCI & \textbf{0.015} & 0.020 & 0.162 & 0.168 \\
341	 & EC-HTE+PPCI & 0.017 & \textbf{0.013} & 0.097 & 0.108 \\
342	\midrule
343	\multirow{5}{*}{B: Outcome}
344	 & Naive & 0.189 & 0.197 & 0.206 & 0.212 \\
345	 & Global & 0.185 & 0.208 & 0.204 & 0.228 \\
346	 & EC-HTE & 0.181 & 0.215 & 0.202 & 0.237 \\
347	 & PPCI & 0.015 & \textbf{0.020} & 0.171 & 0.176 \\
348	 & EC-HTE+PPCI & \textbf{0.012} & 0.023 & 0.171 & 0.186 \\
349	\midrule
350	\multirow{5}{*}{C: Both}
351	 & Naive & 0.251 & 0.135 & 0.267 & 0.155 \\
352	 & Global & 0.182 & 0.209 & 0.233 & 0.235 \\
353	 & EC-HTE & 0.179 & 0.216 & 0.224 & 0.262 \\
354	 & PPCI & 0.017 & 0.007 & 0.241 & 0.232 \\
355	 & EC-HTE+PPCI$^\star$ & \textbf{0.007} & \textbf{0.008} & 0.209 & 0.223 \\
356	\midrule
357	\multirow{5}{*}{D: None}
358	 & Naive & \textbf{0.007} & 0.003 & 0.060 & 0.065 \\
359	 & Global & 0.010 & \textbf{0.002} & 0.061 & 0.071 \\
360	 & EC-HTE & 0.013 & 0.007 & 0.062 & 0.079 \\
361	 & PPCI & \textbf{0.007} & \textbf{0.003} & 0.060 & 0.065 \\
362	 & EC-HTE+PPCI & 0.013 & 0.007 & 0.062 & 0.079 \\
363	\bottomrule
364	\end{tabular}
365	\end{table*}
366	
367	The orthogonality of EC-HTE and PPCI follows from the distinct error sources they correct: EC-HTE addresses misclassification in the effect modifier $Z$ (covariate space), while PPCI corrects specification error in the outcome model $f(X)$ (prediction space).
368	Since covariate misclassification and outcome model error are algebraically independent in the potential outcomes framework, their corrections compose without interference---confirmed by the 4-DGP orthogonal design (Table~\ref{tab:ppci}), where DGP~C (both errors present) yields the largest bias reduction from the combined approach.
369	Under covariate error only, PPCI adds nothing; under no error, all methods perform equivalently.
370	
371	\section{Real-Data Case Study: Hate Speech Detection}
372	\label{app:hatespeech}
373	
374	We apply EC-HTE to the UC Berkeley Measuring Hate Speech corpus~\cite{kennedy2020constructing}, annotating 2{,}496 comments for dehumanization using GPT-4.1.
375	Four text-feature subgroups are defined by crossing platform (Reddit/Gab vs.\ Twitter/YouTube) and text length (above/below median), yielding balanced groups ($n \approx 624$ each).
376	
377	\paragraph{Positive finding: real-world heterogeneity.}
378	Per-subgroup misclassification rates range from 0.266 to 0.383, confirming heterogeneity ($\Delta\pi = 0.117$) in a real annotation setting.
379	At the error-type level, FPR ranges from 8.5\% to 21.3\% across text-feature subgroups, demonstrating that subgroup-varying misclassification is not an artifact of synthetic design but arises naturally in real NLP annotation tasks.
380	
381	\paragraph{Boundary condition: statistical power at extreme FNR.}
382	Correction results are inconclusive: all corrected confidence intervals contain zero, and point estimate differences between methods are not statistically significant.
383	The high baseline FNR (53.3\%) amplifies variance through matrix inversion (variance amplification factor up to 15.7$\times$), rendering the comparison underpowered.
384	When $P(\hat{Z}{=}1 \mid Z{=}1) \approx 0.5$, the confusion matrix approaches singularity, and inversion amplifies estimation noise regardless of stratification strategy.
385	This complements the expert budget threshold identified in Section~\ref{sec:budget}: EC-HTE requires \emph{both} sufficient expert labels \emph{and} sufficient baseline classifier quality.
386	
387	\paragraph{Diagnostic connection.}
388	The diagnostic criterion ($\Delta\pi \times \Delta\tau$, Section~\ref{sec:diagnostic}) identifies when correction is worthwhile under moderate baseline accuracy.
389	This case study illustrates that even when $\Delta\pi$ is large, extreme baseline error renders correction underpowered rather than beneficial.
390	A practical prerequisite is that the per-subgroup confusion matrix condition number $\kappa(\hat{C}_s)$ remain moderate; when $\kappa > 50$, as observed here, practitioners should prioritize improving annotation quality before applying any matrix-inversion-based correction.
391	
392	\section{Cross-Model Consistency}
393	\label{app:multilm}
394	
395	We evaluate whether misclassification heterogeneity is model-specific by annotating 500 TweetEval sentiment tweets with six OpenAI models spanning three generations.
396	Six text-feature subgroups are defined by crossing hashtag presence and text length.
397	Spearman rank correlations of per-subgroup error rates across all six subgroups range from $\rho = 0.82$ to $1.00$, indicating that the subgroup error structure is consistent across architectures.
398	Two subgroups with $n \leq 6$ exhibit zero misclassification across all models; excluding these yields four-point correlations that are directionally consistent but underpowered.%
399	\footnote{The filtered $\Delta\pi$ values in Table~\ref{tab:multilm} serve as a robustness check independent of rank-order testing: all six models exceed $\Delta\pi > 0.05$ on the four retained subgroups.}
400	
401	\begin{table}[t]
402	\centering
403	\caption{Effective misclassification heterogeneity ($\Delta\pi$) across six OpenAI models on TweetEval sentiment (500 tweets, filtered to 4 subgroups with $n \geq 10$).}
404	\label{tab:multilm}
405	\small
406	\begin{tabular}{lcc}
407	\toprule
408	Model & Effective $\Delta\pi$ & $> 0.05$? \\
409	\midrule
410	GPT-3.5-Turbo & 0.198 & \checkmark \\
411	GPT-4-Turbo & 0.149 & \checkmark \\
412	GPT-4o-mini & 0.136 & \checkmark \\
413	GPT-5.4 & 0.114 & \checkmark \\
414	GPT-4.1 & 0.098 & \checkmark \\
415	GPT-4o & 0.080 & \checkmark \\
416	\bottomrule
417	\end{tabular}
418	\end{table}
419	
420	All six models exhibit effective $\Delta\pi > 0.05$ on the four retained subgroups (Table~\ref{tab:multilm}), and 5 of 6 share the same worst subgroup (\texttt{True\_medium}: tweets with hashtags and medium text length).
421	Newer models reduce absolute error rates but do not eliminate subgroup heterogeneity: GPT-5.4 achieves $\Delta\pi = 0.114$ compared to GPT-3.5-Turbo's $0.198$.
422	These results were obtained with a single API provider; cross-provider validation is left to future work.
423	
424	\section{Robustness to Subgroup Misspecification}
425	\label{app:robustness}
426	
427	EC-HTE requires pre-defined subgroup labels, which may be noisy in practice.
428	We test robustness by randomly flipping each observation's subgroup assignment with probability $p_{\text{flip}} \in \{0, 0.10, 0.25, 0.50\}$, across $K \in \{2, 4\}$ (extreme regime, $n_{\text{expert}} = 500$, $\Delta\tau = 0.3$, 100 MC runs).
429	
430	\begin{table}[t]
431	\centering
432	\caption{95\% CI coverage under subgroup misspecification noise. EC-HTE maintains near-nominal coverage across all noise levels.}
433	\label{tab:robustness}
434	\small
435	\begin{tabular}{lcccc}
436	\toprule
437	& \multicolumn{4}{c}{$p_{\text{flip}}$} \\
438	\cmidrule(lr){2-5}
439	Method & 0.00 & 0.10 & 0.25 & 0.50 \\
440	\midrule
441	\multicolumn{5}{l}{\textit{$K{=}2$, extreme}} \\
442	\quad Naive & 0.875 & 0.877 & 0.890 & 0.897 \\
443	\quad Global & 0.925 & 0.935 & 0.932 & 0.945 \\
444	\quad HB EC-HTE & 0.958 & 0.948 & 0.950 & 0.945 \\
445	\midrule
446	\multicolumn{5}{l}{\textit{$K{=}4$, extreme}} \\
447	\quad Naive & 0.904 & 0.916 & 0.909 & 0.919 \\
448	\quad Global & 0.930 & 0.953 & 0.948 & 0.944 \\
449	\quad HB EC-HTE & 0.956 & 0.958 & 0.960 & 0.946 \\
450	\bottomrule
451	\end{tabular}
452	\end{table}
453	
454	EC-HTE maintains coverage $\geq 0.945$ across all configurations (Table~\ref{tab:robustness}), while the naive estimator is systematically below nominal (0.875--0.919).
455	At $p_{\text{flip}} = 0.50$, subgroup structure is effectively destroyed; EC-HTE converges to global correction (coverage and RMSE within 0.1\%), confirming that hierarchical Bayesian shrinkage provides a built-in safety mechanism.
456	For $K{=}4$ at $p_{\text{flip}} = 0.50$, a small residual RMSE gap persists ($p < 0.01$), reflecting the variance cost of estimating four confusion matrices even when they carry no signal.
457	
458	\section{Monte Carlo Standard Errors}
459	\label{app:mcse}
460	
461	All experiments use 100 independent Monte Carlo replications per configuration.
462	All simulation results were verified with 100 MC seeds; the median RMSE variation between 50-seed and 100-seed estimates is below 3.2\%, confirming the stability of reported figures.
463	We report Monte Carlo standard errors to assess whether observed differences between methods are statistically reliable.
464	For exp-001 (synthetic DGP, no per-seed pairing across methods), we use conservative two-sample $z$-tests on the 100-run means.
465	For exp-003 (semi-synthetic TweetEval, shared seeds across methods), we use paired $t$-tests, which are more powerful because they control for seed-level variation.
466	
467	Table~\ref{tab:mcse} reports paired comparisons for representative configurations.
468	Of 1{,}020 total pairwise comparisons across all configurations, 742 (72.7\%) are statistically significant at $\alpha = 0.05$.
469	
470	\begin{table}[t]
471	\centering
472	\caption{Paired comparisons for representative configurations. $\Delta$ = method A $-$ method B (negative favors A for $|\text{bias}|$). Two-sample $z$-tests for synthetic (exp-001); paired $t$-tests for semi-synthetic (exp-003). Bold $p$-values indicate significance at $\alpha = 0.05$.}
473	\label{tab:mcse}
474	\small
475	\begin{tabular}{llrr}
476	\toprule
477	Configuration & Comparison & $\Delta$ & $p$ \\
478	\midrule
479	\multicolumn{4}{l}{\textit{HB EC-HTE vs.\ Global ($|\text{bias}|$)}} \\
480	\quad $K{=}2$/ext/$n{=}500$ & & $-0.046$ & $\mathbf{<0.001}$ \\
481	\quad $K{=}4$/ext/$n{=}500$ & & $-0.078$ & $\mathbf{<0.001}$ \\
482	\quad $K{=}4$/mod/$n{=}250$ & & $-0.017$ & $0.288$ \\
483	\quad TweetEval/ext/$n{=}250$ & & $+0.001$ & $0.395$ \\
484	\midrule
485	\multicolumn{4}{l}{\textit{HB EC-HTE vs.\ Global (RMSE)}} \\
486	\quad $K{=}2$/ext/$n{=}500$ & & $+0.015$ & $0.179$ \\
487	\quad $K{=}4$/ext/$n{=}500$ & & $+0.048$ & $\mathbf{0.011}$ \\
488	\midrule
489	\multicolumn{4}{l}{\textit{HB EC-HTE vs.\ Naive ($|\text{bias}|$)}} \\
490	\quad $K{=}2$/ext/$n{=}500$ & & $-0.089$ & $\mathbf{<0.001}$ \\
491	\quad $K{=}4$/ext/$n{=}500$ & & $-0.113$ & $\mathbf{<0.001}$ \\
492	\quad $K{=}4$/mod/$n{=}250$ & & $-0.031$ & $\mathbf{0.038}$ \\
493	\quad TweetEval/ext/$n{=}250$ & & $+0.005$ & $\mathbf{0.030}$ \\
494	\bottomrule
495	\end{tabular}
496	\end{table}
497	
498	Under extreme heterogeneity, HB EC-HTE's bias advantage over global correction is highly significant ($p < 0.001$ for both $K{=}2$ and $K{=}4$).
499	The RMSE penalty of stratification is not significant at $K{=}2$ ($p = 0.179$) but reaches significance at $K{=}4$ ($p = 0.011$), consistent with the higher variance cost of estimating four confusion matrices.
500	Under moderate heterogeneity ($K{=}4$, $n{=}250$), the bias difference between HB and global is not significant ($p = 0.288$), confirming that EC-HTE's advantage requires sufficient error heterogeneity.
501	In the semi-synthetic TweetEval experiment, HB EC-HTE does not significantly improve over global ($p = 0.395$), consistent with moderate $\Delta\pi$ and unbalanced subgroup sizes.
502	The HB vs.\ naive comparison in TweetEval is significant ($p = 0.030$) but favors naive, reflecting the variance cost of stratification when bias reduction is marginal.
503	
504	\section{Semi-Real Confusion Matrix Validation}
505	\label{app:semireal}
506	
507	We test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.
508	Four text-feature subgroups ($K{=}4$) retain the real per-subgroup FPR and FNR from pilot annotations (Table~\ref{tab:semireal_cm}); CATE heterogeneity is injected synthetically ($\tau(z{=}0,s) = 0.3 + 0.1s$, $\tau(z{=}1,s) = 0.8 - 0.15s$).
509	$N{=}5{,}000$, $P(Z{=}1){=}0.18$, 100 MC seeds per $n_{\text{expert}}$ level.
510	
511	\begin{table}[t]
512	\centering
513	\caption{Empirical confusion matrices from GPT-4.1 TweetEval pilot.
514	S0 exhibits FNR $= 0.526$, approaching chance-level classification.}
515	\label{tab:semireal_cm}
516	\small
517	\begin{tabular}{lcccc}
518	\toprule
519	Subgroup & Weight & FPR & FNR & $\kappa(\hat{C}_s)$ \\
520	\midrule
521	S0 & 0.38 & 0.054 & 0.526 & high \\
522	S1 & 0.22 & 0.101 & 0.300 & moderate \\
523	S2 & 0.14 & 0.143 & 0.308 & moderate \\
524	S3 & 0.25 & 0.194 & 0.222 & low \\
525	\bottomrule
526	\end{tabular}
527	\end{table}
528	
529	\begin{table}[t]
530	\centering
531	\caption{Semi-real confusion matrix results. RMSE and coverage averaged over subgroups and $z$-levels (100 MC runs). HB EC-HTE underperforms global at all budgets; S0's near-chance FNR drives the failure.}
532	\label{tab:semireal}
533	\small
534	\begin{tabular}{llcc}
535	\toprule
536	$n_{\text{expert}}$ & Method & RMSE $\downarrow$ & Coverage $\uparrow$ \\
537	\midrule
538	\multirow{4}{*}{100}
539	 & Oracle & 0.101 & 0.957 \\
540	 & Naive & 0.123 & 0.879 \\
541	 & Global & 0.263 & 0.885 \\
542	 & HB EC-HTE & 0.784 & 0.744 \\
543	\midrule
544	\multirow{4}{*}{250}
545	 & Oracle & 0.101 & 0.957 \\
546	 & Naive & 0.123 & 0.879 \\
547	 & Global & 0.232 & 0.909 \\
548	 & HB EC-HTE & 0.411 & 0.834 \\
549	\midrule
550	\multirow{4}{*}{500}
551	 & Oracle & 0.101 & 0.957 \\
552	 & Naive & 0.123 & 0.879 \\
553	 & Global & 0.196 & 0.922 \\
554	 & HB EC-HTE & 0.260 & 0.890 \\
555	\bottomrule
556	\end{tabular}
557	\end{table}
558	
559	HB EC-HTE produces higher RMSE and lower coverage than global correction at all expert budgets (Table~\ref{tab:semireal}).
560	The root cause is S0's FNR $= 0.526$: when a confusion matrix row approaches a uniform distribution ($P(\hat{Z}{=}1 \mid Z{=}1) \approx 0.5$), inversion amplifies estimation noise regardless of the expert budget.
561	This converges with the hate speech case study (Appendix~\ref{app:hatespeech}, FNR $= 53.3$\%) and confirms that EC-HTE requires \emph{both} sufficient expert labels \emph{and} sufficient baseline classifier quality per subgroup.
562	The singularity guard ($\kappa > 100$, Section~\ref{sec:method}) mitigates catastrophic failure by falling back to global correction for near-degenerate subgroups, but does not recover the bias reduction that motivates stratification.
563	At $n_{\text{expert}} = 500$, HB EC-HTE narrows the gap (RMSE 0.260 vs.\ 0.196) as confusion matrix estimates stabilize for the three well-classified subgroups, but the S0 bottleneck persists.
564	
565	A second semi-real experiment using GPT-3.5-Turbo confusion matrices (worst-subgroup FPR $= 0.39$, FNR $= 0.21$) yields similar results: HB RMSE exceeds global by 1.3--3.5$\times$ at all budgets.
566	Here the failure stems from high false-positive rates compounded by class imbalance ($P(Z{=}1) = 0.18$), which leaves insufficient expert observations in the positive class for reliable per-subgroup confusion matrix estimation.
567	Together, these experiments identify three applicability conditions for EC-HTE: (1)~sufficient effective expert budget ($n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$), (2)~no near-chance subgroup error rate ($\max(\text{FPR}_s, \text{FNR}_s) < 0.5$), and (3)~adequate class balance in the effect modifier.
568	
569	\paragraph{Diagnostic rule.}
570	A logistic regression over all 368 semi-real experiment--budget cells (dependent variable: HB EC-HTE $<$ Global RMSE) identifies two sufficient statistics: the worst-subgroup confusion matrix condition number $\kappa(\hat{M}_s) \leq 1.25$ and the effective minority-class expert count $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$.
571	When both conditions hold, HB outperforms global in 93.3\% of cells; when either is violated, global is preferred in 94.7\% of cells.
572	Both exp-015 ($\kappa = 2.38$, effective $n = 2.5$) and exp-016 ($\kappa = 1.55$, effective $n = 2.5$) violate both conditions, and the diagnostic correctly predicts 100\% of their failure cells.
573	Subgroup-average metrics can mask cell-level heterogeneity: in exp-015, HB EC-HTE substantially reduces bias for the three well-classified subgroups (S1--S3) but amplifies variance in the near-degenerate subgroup (S0, FNR $= 0.526$), and the S0 penalty dominates the aggregate RMSE.
574	
575	\begin{figure}[t]
576	\centering
577	\includegraphics[width=\columnwidth]{figures/applicability_frontier.pdf}
578	\caption{Applicability frontier of EC-HTE. Green region: EC-HTE reduces bias vs.\ global correction. Yellow: comparable performance. Red: EC-HTE underperforms. Dashed lines mark the expert budget threshold ($n_{\text{expert}}/K = 25$) and classifier quality threshold (worst-subgroup error rate $= 0.5$). Red diamonds show semi-real experiments with actual GPT-4.1 and GPT-3.5-Turbo confusion matrices.}
579	\label{fig:applicability}
580	\end{figure}
581	
582	\section{Robustness: Estimator Choice and Treatment Effect Specification}
583	\label{app:rlearner}
584	
585	We verify that EC-HTE's corrected pseudo-outcomes are compatible with downstream estimators beyond CausalForest by replacing it with the R-learner~\citep{nie2021quasi}.
586	The experiment uses $K{=}2$, extreme heterogeneity, $n_{\text{expert}} = 500$, and 50 MC seeds; the R-learner uses 5-fold cross-fitting with gradient-boosted trees as the base learner.
587	
588	\begin{table}[t]
589	\centering
590	\caption{R-learner vs.\ CausalForest with EC-HTE correction ($K{=}2$, extreme, $n{=}500$). $|\text{Bias}|$ and RMSE averaged over subgroups, $z$-levels, and seeds.}
591	\label{tab:rlearner}
592	\small
593	\begin{tabular}{llccc}
594	\toprule
595	Estimator & Correction & $|\text{Bias}|$ & RMSE & Cov. \\
596	\midrule
597	\multirow{4}{*}{R-learner}
598	 & Oracle & 0.006 & 0.056 & 0.94 \\
599	 & Naive & 0.121 & 0.139 & 0.47 \\
600	 & Global & 0.098 & 0.123 & 0.72 \\
601	 & EC-HTE & \textbf{0.013} & 0.080 & 0.92 \\
602	\midrule
603	\multirow{2}{*}{CausalForest}
604	 & Naive & 0.058 & 0.090 & 0.82 \\
605	 & EC-HTE & \textbf{0.011} & 0.093 & 0.95 \\
606	\bottomrule
607	\end{tabular}
608	\end{table}
609	
610	EC-HTE reduces R-learner $|\text{bias}|$ by 89\% (0.121 $\to$ 0.013) and restores coverage from 0.47 to 0.92 (Table~\ref{tab:rlearner}).
611	The bias reduction and coverage gains are comparable to those achieved with CausalForest, confirming that EC-HTE functions as an estimator-agnostic upstream correction.
612	
613	\paragraph{Multiplicative treatment effects.}
614	We further test robustness to the functional form of treatment effects by replacing the additive DGP with a multiplicative specification: $Y(1) = Y(0) \times \exp(\tau(Z))$, using $K{=}2$, extreme heterogeneity, $n_{\text{expert}} = 500$, and 50 MC seeds.
615	
616	\begin{table}[t]
617	\centering
618	\caption{Multiplicative DGP results ($K{=}2$, extreme, $n{=}500$, 50 seeds). EC-HTE achieves comparable bias reduction and nominal coverage under non-additive treatment effects.}
619	\label{tab:multiplicative}
620	\small
621	\begin{tabular}{lccc}
622	\toprule
623	Method & $|\text{Bias}|$ & RMSE & Cov. \\
624	\midrule
625	Oracle & 0.003 & 0.038 & 0.96 \\
626	Naive & 0.135 & 0.142 & 0.44 \\
627	Global & 0.110 & 0.124 & 0.54 \\
628	EC-HTE & \textbf{0.054} & 0.068 & 0.955 \\
629	\bottomrule
630	\end{tabular}
631	\end{table}
632	
633	EC-HTE reduces RMSE by 52\% relative to naive (0.068 vs.\ 0.142) and restores coverage to the nominal level (0.955; Table~\ref{tab:multiplicative}).
634	EC-HTE's bias correction operates at the confusion matrix level, independent of the downstream CATE estimator and functional form of treatment effects.
635	
636	\section{Robustness to Class Imbalance}
637	\label{app:classimbalance}
638	
639	Assumption (A3) requires $P(Z{=}1) = 0.5$, but real-world effect modifiers are often imbalanced.
640	We sweep $P(Z{=}1) \in \{0.1, 0.2, 0.3, 0.4, 0.5\}$ with $K \in \{2,4\}$, extreme misclassification heterogeneity, $n_{\text{expert}}{=}250$, and 100 MC seeds (Table~\ref{tab:pz1_sweep}).
641	
642	\begin{table}[t]
643	\centering
644	\caption{Robustness to class imbalance ($n_{\text{expert}}{=}250$, extreme heterogeneity). R$^2$: Theorem~\ref{thm:bias_identity} fit. Ratio: HB/Global RMSE ($<1$ = HB wins). Cov.: HB EC-HTE 95\% CI coverage.}
645	\label{tab:pz1_sweep}
646	\small
647	\begin{tabular}{cc ccc}
648	\toprule
649	$P(Z{=}1)$ & $K$ & R$^2$ & Ratio & Cov. \\
650	\midrule
651	0.1 & 2 & 0.998 & 0.92 & 0.94 \\
652	0.2 & 2 & 0.989 & 0.76 & 0.94 \\
653	0.3 & 2 & 0.994 & 0.78 & 0.94 \\
654	0.4 & 2 & 0.995 & 0.87 & 0.94 \\
655	0.5 & 2 & 0.995 & 0.86 & 0.93 \\
656	\midrule
657	0.1 & 4 & 0.984 & 1.54 & 0.92 \\
658	0.2 & 4 & 0.976 & 1.68 & 0.93 \\
659	0.3 & 4 & 0.985 & 1.12 & 0.92 \\
660	0.4 & 4 & 0.984 & 1.08 & 0.93 \\
661	0.5 & 4 & 0.992 & 1.06 & 0.92 \\
662	\bottomrule
663	\end{tabular}
664	\end{table}
665	
666	Theorem~\ref{thm:bias_identity}'s product form remains accurate across all imbalance levels: $R^2 \geq 0.976$ even at $P(Z{=}1) = 0.1$, confirming that the bias identity derives from confusion matrix structure rather than class balance.
667	For $K{=}2$, EC-HTE outperforms global correction at all $P(Z{=}1)$ levels (RMSE ratio 0.76--0.92), degrading gracefully under severe imbalance.
668	For $K{=}4$, EC-HTE underperforms global at $n_{\text{expert}}{=}250$ (ratio 1.06--1.68), consistent with the budget threshold $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$: at $P(Z{=}1){=}0.1$, $K{=}4$, each subgroup receives only ${\sim}6$ minority-class labels.
669	The gap narrows as $P(Z{=}1)$ increases (1.54 $\to$ 1.06), and coverage remains stable at 0.92--0.94 across all configurations.
670	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "823daf34-e330-417c-8162-43e1d11ad59e",
  "isSidechain": false,
  "promptId": "500ceecd-d23e-42ba-9539-45d70198290e",
  "type": "user",
  "uuid": "445d9492-e477-4ccf-b142-412a71e99bef",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
      "content": "\\section{EC-HTE Procedure}\n\\label{app:algorithm}\n\n\\begin{algorithm}[t]\n\\caption{EC-HTE: Error-Corrected Heterogeneous Treatment Effects}\n\\label{alg:echte}\n\\begin{algorithmic}[1]\n\\Require Observations $\\{(Y_i, W_i, \\hat{Z}_i, X_i)\\}_{i=1}^N$; expert labels $\\{Z_j^*\\}_{j=1}^{n_{\\text{expert}}}$; subgroup map $S: \\mathcal{X} \\to \\{1,\\ldots,K\\}$\n\\Ensure Corrected CATE estimates $\\hat{\\tau}(z)$ with variance-adjusted CIs\n\\Statex\n\\State \\textbf{Step 1: Estimate per-subgroup confusion matrices (HB)}\n\\For{$s = 1, \\ldots, K$}\n    \\State $C_s[j,\\cdot] \\sim \\mathrm{Dir}(\\alpha_0 \\cdot \\mathbf{e}_j)$, \\; $\\alpha_0 \\sim \\mathrm{Gamma}(3,1)$\n    \\State Gibbs sampler (4 chains, 4000 iter) on $\\{(\\hat{Z}_j, Z_j^*) : S_j = s\\}$\n    \\State $\\hat{C}_s \\gets$ posterior mean; verify $\\hat{R} < 1.01$\n\\EndFor\n\\Statex\n\\State \\textbf{Step 2: Correct observed outcome moments}\n\\For{$s = 1, \\ldots, K$}\n    \\If{$\\kappa(\\hat{C}_s) > 100$} $\\hat{C}_s \\gets \\bar{C}$ \\Comment{singularity guard}\n    \\EndIf\n    \\State $\\tilde{\\boldsymbol{\\mu}}_s \\gets \\hat{C}_s^{-1} \\hat{\\boldsymbol{\\mu}}_s$\n\\EndFor\n\\Statex\n\\State \\textbf{Step 3: CausalForestDML with variance-adjusted SEs}\n\\State Train CausalForest (honest splitting) on corrected labels\n\\State $\\mathrm{se}_{\\mathrm{adj},i} \\gets \\sqrt{\\mathrm{diag}(\\hat{C}_{S_i}^{-1}\\, \\mathrm{diag}(\\mathrm{se}_i^2)\\, \\hat{C}_{S_i}^{-\\top})}$\n\\State \\Return $\\hat{\\tau}(z)$ with 95\\% CIs from $\\mathrm{se}_{\\mathrm{adj}}$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\section{Full Proof of Theorem~\\ref{thm:bias_identity}}\n\\label{app:derivation}\n\n\\paragraph{Setup.}\nUnder assumptions (A1)--(A4), the observed CATE in subgroup $s$ at effect-modifier level $z$ is\n\\begin{equation}\n\\tau_{\\text{obs}}(z, s) = \\sum_{z'} M_s[z, z'] \\cdot \\tau(z'),\n\\end{equation}\nwhere $M_s[z, z'] = P(Z{=}z' \\mid \\hat{Z}{=}z, S{=}s)$ is the mixing matrix.\nUnder (A2)--(A3), $M_s = \\bigl[\\begin{smallmatrix} 1-\\pi_s & \\pi_s \\\\ \\pi_s & 1-\\pi_s \\end{smallmatrix}\\bigr]$.\n\n\\paragraph{Global correction.}\nThe pooled mixing matrix is $M_{\\text{global}} = \\sum_s w_s M_s = \\bigl[\\begin{smallmatrix} 1-\\bar{\\pi} & \\bar{\\pi} \\\\ \\bar{\\pi} & 1-\\bar{\\pi} \\end{smallmatrix}\\bigr]$, with $\\bar{\\pi} = \\sum_s w_s \\pi_s$.\n\nGlobal correction applies $M_{\\text{global}}^{-1}$ to $\\tau_{\\text{obs}}(\\cdot, s)$:\n\\begin{equation}\n\\hat{\\tau}_{\\text{global}}(z, s) = [M_{\\text{global}}^{-1} M_s \\cdot \\boldsymbol{\\tau}]_z,\n\\end{equation}\nwhere $\\boldsymbol{\\tau} = [\\tau(0), \\tau(1)]^\\top$.\n\n\\paragraph{Bias computation.}\nThe bias is $\\hat{\\tau}_{\\text{global}}(z, s) - \\tau(z) = [(M_{\\text{global}}^{-1} M_s - I) \\boldsymbol{\\tau}]_z$.\n\nDirect computation gives:\n\\begin{equation}\nM_{\\text{global}}^{-1} = \\frac{1}{1 - 2\\bar{\\pi}} \\begin{bmatrix} 1-\\bar{\\pi} & -\\bar{\\pi} \\\\ -\\bar{\\pi} & 1-\\bar{\\pi} \\end{bmatrix}.\n\\end{equation}\nMultiplying by $M_s$:\n\\begin{equation}\n\\resizebox{.88\\columnwidth}{!}{$\\displaystyle\nM_{\\text{global}}^{-1} M_s = \\frac{1}{1-2\\bar{\\pi}} \\begin{bmatrix} (1{-}\\bar{\\pi})(1{-}\\pi_s) - \\bar{\\pi}\\pi_s & (1{-}\\bar{\\pi})\\pi_s - \\bar{\\pi}(1{-}\\pi_s) \\\\ -\\bar{\\pi}(1{-}\\pi_s) + (1{-}\\bar{\\pi})\\pi_s & -\\bar{\\pi}\\pi_s + (1{-}\\bar{\\pi})(1{-}\\pi_s) \\end{bmatrix}.\n$}\n\\end{equation}\n\nDefine $\\delta_s = \\pi_s - \\bar{\\pi}$. The $(1,1)$ entry simplifies:\n{\\small\n\\begin{align}\n(1{-}\\bar{\\pi})(1{-}\\pi_s) - \\bar{\\pi}\\pi_s &= 1 - \\bar{\\pi} - \\pi_s + 2\\bar{\\pi}\\pi_s \\nonumber\\\\\n&= (1 - 2\\bar{\\pi}) + (\\bar{\\pi} - \\pi_s) + 2\\bar{\\pi}\\pi_s \\nonumber\\\\\n&= (1 - 2\\bar{\\pi}) - \\delta_s.\n\\end{align}\n}\n\nMore directly, substituting $\\pi_s = \\bar{\\pi} + \\delta_s$:\n\\begin{equation}\nM_{\\text{global}}^{-1} M_s - I = \\frac{\\delta_s}{1-2\\bar{\\pi}} \\begin{bmatrix} -1 & 1 \\\\ 1 & -1 \\end{bmatrix}.\n\\end{equation}\n\nTo verify: the $(1,1)$ entry of $M_{\\text{global}}^{-1} M_s$ is\n{\\small\n\\begin{align}\n&\\frac{(1{-}\\bar{\\pi})(1{-}\\bar{\\pi}{-}\\delta_s) - \\bar{\\pi}(\\bar{\\pi}{+}\\delta_s)}{1-2\\bar{\\pi}} \\nonumber\\\\\n&= \\frac{(1{-}\\bar{\\pi})^2 - (1{-}\\bar{\\pi})\\delta_s - \\bar{\\pi}^2 - \\bar{\\pi}\\delta_s}{1-2\\bar{\\pi}} \\nonumber\\\\\n&= \\frac{1 - 2\\bar{\\pi} - \\delta_s}{1-2\\bar{\\pi}} = 1 - \\frac{\\delta_s}{1-2\\bar{\\pi}}.\n\\end{align}\n}\n\nApplying $(M_{\\text{global}}^{-1} M_s - I)$ to $\\boldsymbol{\\tau}$:\n{\\small\n\\begin{align}\n\\text{bias}(z{=}0, s) &= \\tfrac{\\delta_s}{1-2\\bar{\\pi}}(-\\tau(0) + \\tau(1)) = +\\tfrac{\\delta_s \\cdot \\Delta\\tau}{1-2\\bar{\\pi}}, \\\\\n\\text{bias}(z{=}1, s) &= \\tfrac{\\delta_s}{1-2\\bar{\\pi}}(\\tau(0) - \\tau(1)) = -\\tfrac{\\delta_s \\cdot \\Delta\\tau}{1-2\\bar{\\pi}},\n\\end{align}\n}\nwhere $\\Delta\\tau = \\tau(1) - \\tau(0)$. \\qed\n\n\\section{Multi-class Extension and Proof}\n\\label{app:multiclass}\n\n\\begin{corollary}[Multi-class Extension]\n\\label{cor:multiclass}\nFor $K > 2$ subgroups with $J$ effect-modifier levels, the subgroup bias of global correction generalizes to\n\\begin{equation}\n\\mathrm{bias}_{\\mathrm{global}}(z, s) = \\sum_{j=1}^{J} \\bigl(\\bar{\\pi}_j - \\pi_{s,j}\\bigr) \\cdot \\bigl(\\tau(j) - \\bar{\\tau}\\bigr) \\cdot g(\\bar{\\pi}),\n\\label{eq:multiclass}\n\\end{equation}\nwhere $g(\\bar{\\pi})$ collects the matrix-inversion amplification terms.\\footnote{For $J=3$ with symmetric misclassification (off-diagonal errors uniform), $g(\\bar{\\pi}) = 1/(1 - 3\\bar{\\pi}/2)$, generalizing the $J{=}2$ factor $1/(1-2\\bar{\\pi})$. In general, $g(\\bar{\\pi}) = 1/(1 - J\\bar{\\pi}/(J-1))$.}\nThe essential structure, $\\sum_s w_s (\\bar{\\pi}_j - \\pi_{s,j}) = 0$, ensures that bias redistributes across subgroups rather than vanishing in aggregate.\n\\end{corollary}\n\n\\paragraph{Proof.}\nFor $K > 2$ subgroups with $J$ effect-modifier levels, the subgroup-specific mixing matrix $M_s$ is $J \\times J$ with entries $M_s[j, j'] = P(Z{=}j' \\mid \\hat{Z}{=}j, S{=}s)$.\nThe global mixing matrix is $M_{\\text{global}} = \\sum_s w_s M_s$.\n\nThe bias of global correction in subgroup $s$ at level $z$ is:\n\\begin{equation}\n\\text{bias}_{\\text{global}}(z, s) = [(M_{\\text{global}}^{-1} M_s - I) \\boldsymbol{\\tau}]_z.\n\\end{equation}\n\nWrite $M_s = M_{\\text{global}} + \\Delta_s$ where $\\Delta_s = M_s - M_{\\text{global}}$ satisfies $\\sum_s w_s \\Delta_s = 0$.\nThen $M_{\\text{global}}^{-1} M_s = I + M_{\\text{global}}^{-1} \\Delta_s$, so:\n\\begin{equation}\n\\text{bias}_{\\text{global}}(z, s) = [M_{\\text{global}}^{-1} \\Delta_s \\cdot \\boldsymbol{\\tau}]_z.\n\\end{equation}\n\nFor symmetric misclassification with per-class error rates $\\pi_{s,j}$ and pooled rates $\\bar{\\pi}_j$, the entries of $\\Delta_s$ have the form $\\Delta_s[j,j'] = (\\bar{\\pi}_j - \\pi_{s,j}) \\cdot h(j, j')$ for a function $h$ determined by the off-diagonal redistribution pattern.\nExpanding the matrix-vector product and collecting terms yields:\n\\begin{equation}\n\\text{bias}_{\\text{global}}(z, s) = \\sum_{j=1}^{J} (\\bar{\\pi}_j - \\pi_{s,j}) \\cdot (\\tau(j) - \\bar{\\tau}) \\cdot g(\\bar{\\pi}),\n\\end{equation}\nwhere $g(\\bar{\\pi})$ collects the matrix-inversion amplification terms and $\\bar{\\tau} = \\sum_j P(Z{=}j) \\tau(j)$.\n\nThe essential structure $\\sum_s w_s (\\bar{\\pi}_j - \\pi_{s,j}) = 0$ ensures that the weighted bias across subgroups sums to zero: global correction redistributes bias rather than creating or eliminating it in aggregate. \\qed\n\n\\section{Proof of Proposition~\\ref{prop:debiasing_hurts}}\n\\label{app:debiasing_hurts}\n\nThe naive estimator has bias $\\tau_{\\text{obs}}(z,s) - \\tau(z)$.\nUnder (A2)--(A3), $\\tau_{\\text{obs}}(0,s) = (1-\\pi_s)\\tau(0) + \\pi_s\\tau(1)$, so $\\text{bias}_{\\text{naive}}(0,s) = \\pi_s \\cdot \\Delta\\tau$.\n\nGlobal correction produces larger absolute bias when $|\\text{bias}_{\\text{global}}(0,s)| > |\\text{bias}_{\\text{naive}}(0,s)|$:\n\\begin{equation}\n\\frac{|\\delta_s| \\cdot |\\Delta\\tau|}{|1-2\\bar{\\pi}|} > \\pi_s \\cdot |\\Delta\\tau|.\n\\end{equation}\nSince $\\Delta\\tau \\neq 0$ (otherwise both biases are zero), dividing through gives:\n\\begin{equation}\n\\frac{|\\delta_s|}{(1-2\\bar{\\pi}) \\cdot \\pi_s} > 1,\n\\end{equation}\nwhere we use $1-2\\bar{\\pi} > 0$ from (A4).\n\nFor high-error subgroups ($\\pi_s > \\bar{\\pi}$, so $\\delta_s > 0$): the condition becomes $(\\pi_s - \\bar{\\pi}) / ((1-2\\bar{\\pi})\\pi_s) > 1$, which simplifies to $\\pi_s(1 - 1 + 2\\bar{\\pi}) > \\bar{\\pi}$, i.e., $2\\bar{\\pi}\\pi_s > \\bar{\\pi}$, i.e., $\\pi_s > 0.5$.\nThis is excluded by (A4), so global correction always reduces bias in high-error subgroups.\n\nFor low-error subgroups ($\\pi_s < \\bar{\\pi}$, so $\\delta_s < 0$): the condition becomes $(\\bar{\\pi} - \\pi_s) / ((1-2\\bar{\\pi})\\pi_s) > 1$, which gives $\\pi_s < \\bar{\\pi} / (1 - 2\\bar{\\pi} + 1) = \\bar{\\pi} / (2(1-\\bar{\\pi}))$.\nWhen $\\bar{\\pi} = 0.15$, any subgroup with $\\pi_s < 0.088$ experiences increased bias from global correction. \\qed\n\n\\section{Semi-Synthetic Data Generating Process}\n\\label{app:dgp}\n\n\\paragraph{Synthetic DGP (Sections~\\ref{sec:bias_mechanism}--\\ref{sec:budget}).}\nWe generate $N = 5000$ observations.\nEach observation belongs to one of $K \\in \\{2, 4\\}$ subgroups $S \\in \\{1, \\ldots, K\\}$ with equal weights $w_s = 1/K$.\nThe binary effect modifier $Z \\in \\{0, 1\\}$ is drawn with $P(Z{=}1) = 0.5$.\nTreatment assignment is $T \\sim \\text{Bernoulli}(0.5)$, independent of $Z$ and $S$.\n\nThe outcome is generated as:\n\\begin{equation}\nY = \\tau(Z) \\cdot T + \\varepsilon, \\quad \\varepsilon \\sim \\mathcal{N}(0, 1),\n\\end{equation}\nwhere the CATE function is $\\tau(z) = \\bar{\\tau} + \\Delta\\tau \\cdot (z - 0.5)$ with $\\bar{\\tau} = 0.5$.\nThe CATE heterogeneity $\\Delta\\tau \\in \\{0, 0.2, 0.5, 1.0\\}$ controls the strength of treatment effect variation across levels of $Z$.\n\nMisclassification is symmetric: $\\hat{Z} \\neq Z$ with probability $\\pi_s$ depending on subgroup.\nFor $K{=}2$: $\\pi_1 = \\bar{\\pi} - \\Delta_c/2$, $\\pi_2 = \\bar{\\pi} + \\Delta_c/2$, with $\\bar{\\pi} \\in \\{0.1, 0.2\\}$ and $\\Delta_c \\in \\{0, 0.05, 0.1, 0.15\\}$.\nFor $K{=}4$, extreme regime: $\\pi \\in \\{0.05, 0.10, 0.15, 0.25\\}$; moderate regime: $\\pi \\in \\{0.08, 0.12, 0.16, 0.20\\}$.\n\nExpert labels are drawn as a simple random sample of size $n_{\\text{expert}} \\in \\{50, 100, 250, 500, 1000, 2000\\}$ from the full dataset, with true $Z$ observed for these observations.\n\n\\paragraph{Semi-synthetic DGP (Section~\\ref{sec:ec_hte_eval}).}\nWe sample $N = 5000$ tweets from the TweetEval sentiment corpus ($N_{\\text{pool}} = 57{,}899$).\nSubgroups are defined by crossing \\texttt{has\\_hashtag} $\\times$ \\texttt{text\\_length\\_bin} (short/medium/long), yielding $K = 4$ subgroups with empirical sizes: $S_0 \\approx 38\\%$, $S_1 \\approx 38\\%$, $S_2 \\approx 12\\%$, $S_3 \\approx 12\\%$.\nMisclassification rates in the extreme regime are $\\pi_{S_0} = 0.05$, $\\pi_{S_1} = 0.10$, $\\pi_{S_2} = 0.15$, $\\pi_{S_3} = 0.25$, reflecting empirical evidence that hashtag-heavy text degrades LLM classifier accuracy.\nThe outcome DGP follows the same structure as the synthetic case, with CATE injected onto the real text-derived subgroup structure.\n\n\\paragraph{PPCI DGPs (Section~\\ref{sec:ppci}).}\nFour DGPs isolate error types: (A) covariate error only ($\\sigma_{\\text{outcome}} = 0$), (B) outcome error only ($\\sigma_{\\text{outcome}} = 0.5$), (C) both errors ($\\sigma_{\\text{outcome}} = 0.5$), (D) no error ($\\sigma_{\\text{outcome}} = 0$).\nOutcome-side error is additive Gaussian noise on $Y$.\n\n\\section{Extended Related Work}\n\\label{app:related}\n\n\\paragraph{Measurement error details.}\n\\citet{fuller1987measurement} establish the foundational theory showing that naive regression with mismeasured covariates yields attenuated coefficient estimates.\n\\citet{carroll2006measurement} extend this to nonlinear models.\n\\citet{gustafson2003measurement} develops Bayesian treatments modeling measurement jointly with outcomes.\n\\citet{hu2008nonparametric} provide nonparametric identification using repeated measurements or instruments.\n\n\\paragraph{Annotation model extensions.}\nBeyond the foundational \\citet{dawid1979maximum} model, \\citet{passonneau2014benefits} incorporate item difficulty, \\citet{hovy2013learning} learn annotator competence, and \\citet{paun2018comparing} introduce hierarchical priors sharing information across annotators with varying expertise.\n\n\\paragraph{PPI extensions and text-as-data methods.}\n\\citet{zrnic2024cross} extend PPI via cross-prediction; their active inference framework~\\citep{zrnic2024active} achieves $>$80\\% expert budget savings through adaptive allocation, complementary to our fixed-budget analysis.\n\\citet{grimmer2022text} and \\citet{audinet2025benchmarking} provide broader methodological guidance for text-as-data pipelines without specific correction for causal heterogeneity.\n\n\\paragraph{Treatment vs.\\ effect-modifier misclassification.}\n\\citet{imai2010causal} study treatment misclassification where errors change which arm a unit is assigned to, requiring instrumental variables or partial identification because the fundamental treated-vs-control contrast is corrupted.\nOur problem preserves the treatment contrast ($T$ is observed correctly) but corrupts the heterogeneity structure ($\\hat{Z} \\neq Z$).\nThe ATE remains identified; only conditional effects are biased, which makes exact correction through confusion matrix inversion feasible.\n\n\\section{MCMC Convergence Diagnostics}\n\\label{app:mcmc}\n\nTable~\\ref{tab:mcmc} reports convergence diagnostics for the hierarchical Bayesian confusion matrix estimator across all experimental configurations.\nAll runs use 4 chains with 4000 iterations (2000 warmup) and a $\\text{Gamma}(3, 1)$ hyperprior on the Dirichlet concentration $\\alpha_0$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lcc}\n\\toprule\nDiagnostic & Threshold & Achieved \\\\\n\\midrule\n$\\hat{R}$ (max across all params) & $< 1.01$ & $< 1.0034$ \\\\\nESS (min across all params) & $> 845$ & $> 1618$ \\\\\nDivergent transitions & $= 0$ & $0$ \\\\\nSingularity guard triggers & --- & extreme/$n{=}50$ only \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{MCMC convergence diagnostics for the hierarchical Bayesian estimator. All configurations satisfy convergence criteria with substantial margin.}\n\\label{tab:mcmc}\n\\end{table}\n\n\\paragraph{Hyperprior sensitivity.}\nScaling the $\\text{Gamma}(3, 1)$ hyperprior by factors of $0.5\\times$ to $2\\times$ produces $<$1\\% RMSE variation for $K{=}2$ and $\\sim$4--5\\% for $K{=}4$.\nCoverage remains invariant across the sensitivity range.\nThese results confirm that the hierarchical estimator is robust to prior specification within a reasonable range.\n\n\\section{Diagnostic ROC Curves}\n\\label{app:roc}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig4_roc.png}\n\\caption{ROC curves for the $\\Delta\\tau$-free diagnostic (Proposition~\\ref{prop:debiasing_hurts}): $|\\delta_s|/((1{-}2\\bar\\pi)\\cdot\\pi_s)>1$. (A)~Setting-level ROC (AUC $= 0.89$), compared with the $|\\Delta\\pi \\times \\Delta\\tau|$ product (AUC $= 0.89$) and $\\mathrm{CV}(\\pi_s)$ (AUC $= 0.97$). (B)~Subgroup-level ROC: the $\\Delta\\pi$-only condition (AUC $= 0.87$) substantially outperforms the $|\\Delta\\pi \\times \\Delta\\tau|$ product (AUC $= 0.73$). The $\\Delta\\tau$-free diagnostic depends only on estimable misclassification rates, breaking the circular dependency that would arise if CATE heterogeneity were required.}\n\\label{fig:roc}\n\\end{figure}\n\n\\section{Expert Budget Crossover Curves}\n\\label{app:budget}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig3_budget.pdf}\n\\caption{RMSE vs.\\ expert budget ($n_{\\text{expert}}$) across four regime$\\times K$ combinations. Dashed vertical lines mark crossover points where EC-HTE achieves lower RMSE than global correction: $n{=}250$ ($K{=}2$, extreme), $n{=}1000$ ($K{=}4$, extreme). Under moderate heterogeneity ($K{=}2$), global correction dominates at all budgets. Shaded bands show $\\pm 1$ SD across subgroups within each configuration.}\n\\label{fig:budget}\n\\end{figure*}\n\n\\section{Asymmetric Misclassification Extension}\n\\label{app:asymmetric}\n\nAssumption~(A2) imposes symmetric misclassification ($\\text{FPR}_s = \\text{FNR}_s = \\pi_s$), which simplifies the bias decomposition but is not necessary for it.\nReal LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.\n\n\\paragraph{General bias formula.}\nFor asymmetric confusion matrices $C_s = \\bigl(\\begin{smallmatrix} 1{-}\\text{FPR}_s & \\text{FPR}_s \\\\ \\text{FNR}_s & 1{-}\\text{FNR}_s \\end{smallmatrix}\\bigr)$, define the mixing matrix $M_s$ via Bayesian inversion and the residual matrix $B_s = M_{\\text{global}}^{-1} M_s - I$.\nSince both $M_s$ and $M_{\\text{global}}$ are row-stochastic, $B_s \\mathbf{1} = \\mathbf{0}$.\nDecomposing $\\boldsymbol{\\tau} = \\tau(0)\\mathbf{1} + \\Delta\\tau \\, \\mathbf{e}_1$ gives:\n\\begin{equation}\n\\text{bias}(z, s) = \\Delta\\tau \\cdot [B_s]_{z,1},\n\\end{equation}\nwhere $[B_s]_{z,1}$ depends only on $\\{\\text{FPR}_k, \\text{FNR}_k, w_k\\}$, not on $\\Delta\\tau$.\nUnder~(A2), this reduces to $\\delta_s \\Delta\\tau / (1 - 2\\bar{\\pi})$ (Theorem~\\ref{thm:bias_identity}).\n\n\\paragraph{Empirical validation.}\nWe test three asymmetric configurations ($K{=}2$, $n_{\\text{expert}}{=}250$, 100 MC runs each): \\emph{Cross} (FPR/FNR = 0.10/0.20 vs.\\ 0.25/0.10), \\emph{Co-directional} (0.05/0.15 vs.\\ 0.20/0.30), and \\emph{Extreme} (0.03/0.25 vs.\\ 0.30/0.05).\nRegressing analytic predictions on MC bias yields $R^2 = 0.991$ across all configurations, confirming the product structure under asymmetry.\nTable~\\ref{tab:asymmetric} reports correction performance averaged over subgroups, $z$-levels, and $\\Delta\\tau \\in \\{0.1, \\ldots, 0.5\\}$.\nEC-HTE reduces $|\\text{bias}|$ from 0.025 (global) to 0.006, a $4\\times$ improvement, with lower RMSE (0.033 vs.\\ 0.040) and substantially better coverage (0.90 vs.\\ 0.78).\n\n\\begin{table}[t]\n\\centering\n\\caption{Asymmetric misclassification results ($K{=}2$, $n_{\\text{expert}}{=}250$, 100 MC runs). Values averaged over subgroups, $z$-levels, and $\\Delta\\tau$.}\n\\label{tab:asymmetric}\n\\small\n\\begin{tabular}{l ccc}\n\\toprule\nMethod & $|\\text{Bias}| \\downarrow$ & RMSE $\\downarrow$ & Coverage $\\uparrow$ \\\\\n\\midrule\nNaive & 0.047 & 0.053 & 0.48 \\\\\nGlobal & 0.025 & 0.040 & 0.78 \\\\\nHB EC-HTE & \\textbf{0.006} & \\textbf{0.033} & \\textbf{0.90} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Supplementary Main Results}\n\\label{app:main_supp}\n\n\\begin{table}[t]\n\\centering\n\\caption{Additional configurations from the main experiment. $|\\text{Bias}|$ and RMSE averaged over subgroups, $z$-levels, and 100 MC runs. $^\\dagger$RMSE exceeds Global.}\n\\label{tab:main_supp}\n\\small\n\\begin{tabular}{ll ccc}\n\\toprule\nConfiguration & Method & $|\\text{Bias}|$ & RMSE & Cov. \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{Synthetic DIM\\\\$K{=}2$, moderate, $n{=}250$}}\n & Naive & 0.018 & 0.064 & 0.95 \\\\\n & Global & 0.009 & 0.074 & 0.96 \\\\\n & Strat.\\ MLE & \\textbf{0.005} & 0.075$^\\dagger$ & 0.97 \\\\\n & HB EC-HTE & \\textbf{0.005} & 0.075$^\\dagger$ & 0.97 \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{Semi-synthetic\\\\TweetEval, extreme, $n{=}250$}}\n & Naive & 0.027 & 0.103 & 0.93 \\\\\n & Global & \\textbf{0.023} & 0.124 & 0.92 \\\\\n & Strat.\\ MLE & 0.032 & 0.248$^\\dagger$ & 0.91 \\\\\n & HB EC-HTE & 0.027 & 0.225$^\\dagger$ & 0.91 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{PPCI Complementarity Results}\n\\label{app:ppci}\n\n\\begin{table*}[t]\n\\centering\n\\caption{PPCI complementarity experiment ($K{=}2$, extreme, $n_{\\text{expert}}{=}250$). DGP~A: covariate error only; B: outcome error only ($\\sigma{=}0.5$); C: both errors; D: no error. Values are $|\\text{bias}|$ and RMSE averaged over two subgroups. $^\\star$EC-HTE+PPCI achieves near-zero bias when both error types are present.}\n\\label{tab:ppci}\n\\small\n\\begin{tabular}{ll cccc}\n\\toprule\nDGP & Method & $|\\text{Bias}|_{z=0}$ & $|\\text{Bias}|_{z=1}$ & RMSE$_{z=0}$ & RMSE$_{z=1}$ \\\\\n\\midrule\n\\multirow{5}{*}{A: Covariate}\n & Naive & 0.053 & 0.063 & 0.087 & 0.093 \\\\\n & Global & 0.063 & 0.055 & 0.101 & 0.102 \\\\\n & EC-HTE & 0.017 & \\textbf{0.013} & 0.097 & 0.108 \\\\\n & PPCI & \\textbf{0.015} & 0.020 & 0.162 & 0.168 \\\\\n & EC-HTE+PPCI & 0.017 & \\textbf{0.013} & 0.097 & 0.108 \\\\\n\\midrule\n\\multirow{5}{*}{B: Outcome}\n & Naive & 0.189 & 0.197 & 0.206 & 0.212 \\\\\n & Global & 0.185 & 0.208 & 0.204 & 0.228 \\\\\n & EC-HTE & 0.181 & 0.215 & 0.202 & 0.237 \\\\\n & PPCI & 0.015 & \\textbf{0.020} & 0.171 & 0.176 \\\\\n & EC-HTE+PPCI & \\textbf{0.012} & 0.023 & 0.171 & 0.186 \\\\\n\\midrule\n\\multirow{5}{*}{C: Both}\n & Naive & 0.251 & 0.135 & 0.267 & 0.155 \\\\\n & Global & 0.182 & 0.209 & 0.233 & 0.235 \\\\\n & EC-HTE & 0.179 & 0.216 & 0.224 & 0.262 \\\\\n & PPCI & 0.017 & 0.007 & 0.241 & 0.232 \\\\\n & EC-HTE+PPCI$^\\star$ & \\textbf{0.007} & \\textbf{0.008} & 0.209 & 0.223 \\\\\n\\midrule\n\\multirow{5}{*}{D: None}\n & Naive & \\textbf{0.007} & 0.003 & 0.060 & 0.065 \\\\\n & Global & 0.010 & \\textbf{0.002} & 0.061 & 0.071 \\\\\n & EC-HTE & 0.013 & 0.007 & 0.062 & 0.079 \\\\\n & PPCI & \\textbf{0.007} & \\textbf{0.003} & 0.060 & 0.065 \\\\\n & EC-HTE+PPCI & 0.013 & 0.007 & 0.062 & 0.079 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\nThe orthogonality of EC-HTE and PPCI follows from the distinct error sources they correct: EC-HTE addresses misclassification in the effect modifier $Z$ (covariate space), while PPCI corrects specification error in the outcome model $f(X)$ (prediction space).\nSince covariate misclassification and outcome model error are algebraically independent in the potential outcomes framework, their corrections compose without interference---confirmed by the 4-DGP orthogonal design (Table~\\ref{tab:ppci}), where DGP~C (both errors present) yields the largest bias reduction from the combined approach.\nUnder covariate error only, PPCI adds nothing; under no error, all methods perform equivalently.\n\n\\section{Real-Data Case Study: Hate Speech Detection}\n\\label{app:hatespeech}\n\nWe apply EC-HTE to the UC Berkeley Measuring Hate Speech corpus~\\cite{kennedy2020constructing}, annotating 2{,}496 comments for dehumanization using GPT-4.1.\nFour text-feature subgroups are defined by crossing platform (Reddit/Gab vs.\\ Twitter/YouTube) and text length (above/below median), yielding balanced groups ($n \\approx 624$ each).\n\n\\paragraph{Positive finding: real-world heterogeneity.}\nPer-subgroup misclassification rates range from 0.266 to 0.383, confirming heterogeneity ($\\Delta\\pi = 0.117$) in a real annotation setting.\nAt the error-type level, FPR ranges from 8.5\\% to 21.3\\% across text-feature subgroups, demonstrating that subgroup-varying misclassification is not an artifact of synthetic design but arises naturally in real NLP annotation tasks.\n\n\\paragraph{Boundary condition: statistical power at extreme FNR.}\nCorrection results are inconclusive: all corrected confidence intervals contain zero, and point estimate differences between methods are not statistically significant.\nThe high baseline FNR (53.3\\%) amplifies variance through matrix inversion (variance amplification factor up to 15.7$\\times$), rendering the comparison underpowered.\nWhen $P(\\hat{Z}{=}1 \\mid Z{=}1) \\approx 0.5$, the confusion matrix approaches singularity, and inversion amplifies estimation noise regardless of stratification strategy.\nThis complements the expert budget threshold identified in Section~\\ref{sec:budget}: EC-HTE requires \\emph{both} sufficient expert labels \\emph{and} sufficient baseline classifier quality.\n\n\\paragraph{Diagnostic connection.}\nThe diagnostic criterion ($\\Delta\\pi \\times \\Delta\\tau$, Section~\\ref{sec:diagnostic}) identifies when correction is worthwhile under moderate baseline accuracy.\nThis case study illustrates that even when $\\Delta\\pi$ is large, extreme baseline error renders correction underpowered rather than beneficial.\nA practical prerequisite is that the per-subgroup confusion matrix condition number $\\kappa(\\hat{C}_s)$ remain moderate; when $\\kappa > 50$, as observed here, practitioners should prioritize improving annotation quality before applying any matrix-inversion-based correction.\n\n\\section{Cross-Model Consistency}\n\\label{app:multilm}\n\nWe evaluate whether misclassification heterogeneity is model-specific by annotating 500 TweetEval sentiment tweets with six OpenAI models spanning three generations.\nSix text-feature subgroups are defined by crossing hashtag presence and text length.\nSpearman rank correlations of per-subgroup error rates across all six subgroups range from $\\rho = 0.82$ to $1.00$, indicating that the subgroup error structure is consistent across architectures.\nTwo subgroups with $n \\leq 6$ exhibit zero misclassification across all models; excluding these yields four-point correlations that are directionally consistent but underpowered.%\n\\footnote{The filtered $\\Delta\\pi$ values in Table~\\ref{tab:multilm} serve as a robustness check independent of rank-order testing: all six models exceed $\\Delta\\pi > 0.05$ on the four retained subgroups.}\n\n\\begin{table}[t]\n\\centering\n\\caption{Effective misclassification heterogeneity ($\\Delta\\pi$) across six OpenAI models on TweetEval sentiment (500 tweets, filtered to 4 subgroups with $n \\geq 10$).}\n\\label{tab:multilm}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\nModel & Effective $\\Delta\\pi$ & $> 0.05$? \\\\\n\\midrule\nGPT-3.5-Turbo & 0.198 & \\checkmark \\\\\nGPT-4-Turbo & 0.149 & \\checkmark \\\\\nGPT-4o-mini & 0.136 & \\checkmark \\\\\nGPT-5.4 & 0.114 & \\checkmark \\\\\nGPT-4.1 & 0.098 & \\checkmark \\\\\nGPT-4o & 0.080 & \\checkmark \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll six models exhibit effective $\\Delta\\pi > 0.05$ on the four retained subgroups (Table~\\ref{tab:multilm}), and 5 of 6 share the same worst subgroup (\\texttt{True\\_medium}: tweets with hashtags and medium text length).\nNewer models reduce absolute error rates but do not eliminate subgroup heterogeneity: GPT-5.4 achieves $\\Delta\\pi = 0.114$ compared to GPT-3.5-Turbo's $0.198$.\nThese results were obtained with a single API provider; cross-provider validation is left to future work.\n\n\\section{Robustness to Subgroup Misspecification}\n\\label{app:robustness}\n\nEC-HTE requires pre-defined subgroup labels, which may be noisy in practice.\nWe test robustness by randomly flipping each observation's subgroup assignment with probability $p_{\\text{flip}} \\in \\{0, 0.10, 0.25, 0.50\\}$, across $K \\in \\{2, 4\\}$ (extreme regime, $n_{\\text{expert}} = 500$, $\\Delta\\tau = 0.3$, 100 MC runs).\n\n\\begin{table}[t]\n\\centering\n\\caption{95\\% CI coverage under subgroup misspecification noise. EC-HTE maintains near-nominal coverage across all noise levels.}\n\\label{tab:robustness}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{4}{c}{$p_{\\text{flip}}$} \\\\\n\\cmidrule(lr){2-5}\nMethod & 0.00 & 0.10 & 0.25 & 0.50 \\\\\n\\midrule\n\\multicolumn{5}{l}{\\textit{$K{=}2$, extreme}} \\\\\n\\quad Naive & 0.875 & 0.877 & 0.890 & 0.897 \\\\\n\\quad Global & 0.925 & 0.935 & 0.932 & 0.945 \\\\\n\\quad HB EC-HTE & 0.958 & 0.948 & 0.950 & 0.945 \\\\\n\\midrule\n\\multicolumn{5}{l}{\\textit{$K{=}4$, extreme}} \\\\\n\\quad Naive & 0.904 & 0.916 & 0.909 & 0.919 \\\\\n\\quad Global & 0.930 & 0.953 & 0.948 & 0.944 \\\\\n\\quad HB EC-HTE & 0.956 & 0.958 & 0.960 & 0.946 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nEC-HTE maintains coverage $\\geq 0.945$ across all configurations (Table~\\ref{tab:robustness}), while the naive estimator is systematically below nominal (0.875--0.919).\nAt $p_{\\text{flip}} = 0.50$, subgroup structure is effectively destroyed; EC-HTE converges to global correction (coverage and RMSE within 0.1\\%), confirming that hierarchical Bayesian shrinkage provides a built-in safety mechanism.\nFor $K{=}4$ at $p_{\\text{flip}} = 0.50$, a small residual RMSE gap persists ($p < 0.01$), reflecting the variance cost of estimating four confusion matrices even when they carry no signal.\n\n\\section{Monte Carlo Standard Errors}\n\\label{app:mcse}\n\nAll experiments use 100 independent Monte Carlo replications per configuration.\nAll simulation results were verified with 100 MC seeds; the median RMSE variation between 50-seed and 100-seed estimates is below 3.2\\%, confirming the stability of reported figures.\nWe report Monte Carlo standard errors to assess whether observed differences between methods are statistically reliable.\nFor exp-001 (synthetic DGP, no per-seed pairing across methods), we use conservative two-sample $z$-tests on the 100-run means.\nFor exp-003 (semi-synthetic TweetEval, shared seeds across methods), we use paired $t$-tests, which are more powerful because they control for seed-level variation.\n\nTable~\\ref{tab:mcse} reports paired comparisons for representative configurations.\nOf 1{,}020 total pairwise comparisons across all configurations, 742 (72.7\\%) are statistically significant at $\\alpha = 0.05$.\n\n\\begin{table}[t]\n\\centering\n\\caption{Paired comparisons for representative configurations. $\\Delta$ = method A $-$ method B (negative favors A for $|\\text{bias}|$). Two-sample $z$-tests for synthetic (exp-001); paired $t$-tests for semi-synthetic (exp-003). Bold $p$-values indicate significance at $\\alpha = 0.05$.}\n\\label{tab:mcse}\n\\small\n\\begin{tabular}{llrr}\n\\toprule\nConfiguration & Comparison & $\\Delta$ & $p$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{HB EC-HTE vs.\\ Global ($|\\text{bias}|$)}} \\\\\n\\quad $K{=}2$/ext/$n{=}500$ & & $-0.046$ & $\\mathbf{<0.001}$ \\\\\n\\quad $K{=}4$/ext/$n{=}500$ & & $-0.078$ & $\\mathbf{<0.001}$ \\\\\n\\quad $K{=}4$/mod/$n{=}250$ & & $-0.017$ & $0.288$ \\\\\n\\quad TweetEval/ext/$n{=}250$ & & $+0.001$ & $0.395$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{HB EC-HTE vs.\\ Global (RMSE)}} \\\\\n\\quad $K{=}2$/ext/$n{=}500$ & & $+0.015$ & $0.179$ \\\\\n\\quad $K{=}4$/ext/$n{=}500$ & & $+0.048$ & $\\mathbf{0.011}$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{HB EC-HTE vs.\\ Naive ($|\\text{bias}|$)}} \\\\\n\\quad $K{=}2$/ext/$n{=}500$ & & $-0.089$ & $\\mathbf{<0.001}$ \\\\\n\\quad $K{=}4$/ext/$n{=}500$ & & $-0.113$ & $\\mathbf{<0.001}$ \\\\\n\\quad $K{=}4$/mod/$n{=}250$ & & $-0.031$ & $\\mathbf{0.038}$ \\\\\n\\quad TweetEval/ext/$n{=}250$ & & $+0.005$ & $\\mathbf{0.030}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nUnder extreme heterogeneity, HB EC-HTE's bias advantage over global correction is highly significant ($p < 0.001$ for both $K{=}2$ and $K{=}4$).\nThe RMSE penalty of stratification is not significant at $K{=}2$ ($p = 0.179$) but reaches significance at $K{=}4$ ($p = 0.011$), consistent with the higher variance cost of estimating four confusion matrices.\nUnder moderate heterogeneity ($K{=}4$, $n{=}250$), the bias difference between HB and global is not significant ($p = 0.288$), confirming that EC-HTE's advantage requires sufficient error heterogeneity.\nIn the semi-synthetic TweetEval experiment, HB EC-HTE does not significantly improve over global ($p = 0.395$), consistent with moderate $\\Delta\\pi$ and unbalanced subgroup sizes.\nThe HB vs.\\ naive comparison in TweetEval is significant ($p = 0.030$) but favors naive, reflecting the variance cost of stratification when bias reduction is marginal.\n\n\\section{Semi-Real Confusion Matrix Validation}\n\\label{app:semireal}\n\nWe test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.\nFour text-feature subgroups ($K{=}4$) retain the real per-subgroup FPR and FNR from pilot annotations (Table~\\ref{tab:semireal_cm}); CATE heterogeneity is injected synthetically ($\\tau(z{=}0,s) = 0.3 + 0.1s$, $\\tau(z{=}1,s) = 0.8 - 0.15s$).\n$N{=}5{,}000$, $P(Z{=}1){=}0.18$, 100 MC seeds per $n_{\\text{expert}}$ level.\n\n\\begin{table}[t]\n\\centering\n\\caption{Empirical confusion matrices from GPT-4.1 TweetEval pilot.\nS0 exhibits FNR $= 0.526$, approaching chance-level classification.}\n\\label{tab:semireal_cm}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nSubgroup & Weight & FPR & FNR & $\\kappa(\\hat{C}_s)$ \\\\\n\\midrule\nS0 & 0.38 & 0.054 & 0.526 & high \\\\\nS1 & 0.22 & 0.101 & 0.300 & moderate \\\\\nS2 & 0.14 & 0.143 & 0.308 & moderate \\\\\nS3 & 0.25 & 0.194 & 0.222 & low \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Semi-real confusion matrix results. RMSE and coverage averaged over subgroups and $z$-levels (100 MC runs). HB EC-HTE underperforms global at all budgets; S0's near-chance FNR drives the failure.}\n\\label{tab:semireal}\n\\small\n\\begin{tabular}{llcc}\n\\toprule\n$n_{\\text{expert}}$ & Method & RMSE $\\downarrow$ & Coverage $\\uparrow$ \\\\\n\\midrule\n\\multirow{4}{*}{100}\n & Oracle & 0.101 & 0.957 \\\\\n & Naive & 0.123 & 0.879 \\\\\n & Global & 0.263 & 0.885 \\\\\n & HB EC-HTE & 0.784 & 0.744 \\\\\n\\midrule\n\\multirow{4}{*}{250}\n & Oracle & 0.101 & 0.957 \\\\\n & Naive & 0.123 & 0.879 \\\\\n & Global & 0.232 & 0.909 \\\\\n & HB EC-HTE & 0.411 & 0.834 \\\\\n\\midrule\n\\multirow{4}{*}{500}\n & Oracle & 0.101 & 0.957 \\\\\n & Naive & 0.123 & 0.879 \\\\\n & Global & 0.196 & 0.922 \\\\\n & HB EC-HTE & 0.260 & 0.890 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nHB EC-HTE produces higher RMSE and lower coverage than global correction at all expert budgets (Table~\\ref{tab:semireal}).\nThe root cause is S0's FNR $= 0.526$: when a confusion matrix row approaches a uniform distribution ($P(\\hat{Z}{=}1 \\mid Z{=}1) \\approx 0.5$), inversion amplifies estimation noise regardless of the expert budget.\nThis converges with the hate speech case study (Appendix~\\ref{app:hatespeech}, FNR $= 53.3$\\%) and confirms that EC-HTE requires \\emph{both} sufficient expert labels \\emph{and} sufficient baseline classifier quality per subgroup.\nThe singularity guard ($\\kappa > 100$, Section~\\ref{sec:method}) mitigates catastrophic failure by falling back to global correction for near-degenerate subgroups, but does not recover the bias reduction that motivates stratification.\nAt $n_{\\text{expert}} = 500$, HB EC-HTE narrows the gap (RMSE 0.260 vs.\\ 0.196) as confusion matrix estimates stabilize for the three well-classified subgroups, but the S0 bottleneck persists.\n\nA second semi-real experiment using GPT-3.5-Turbo confusion matrices (worst-subgroup FPR $= 0.39$, FNR $= 0.21$) yields similar results: HB RMSE exceeds global by 1.3--3.5$\\times$ at all budgets.\nHere the failure stems from high false-positive rates compounded by class imbalance ($P(Z{=}1) = 0.18$), which leaves insufficient expert observations in the positive class for reliable per-subgroup confusion matrix estimation.\nTogether, these experiments identify three applicability conditions for EC-HTE: (1)~sufficient effective expert budget ($n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$), (2)~no near-chance subgroup error rate ($\\max(\\text{FPR}_s, \\text{FNR}_s) < 0.5$), and (3)~adequate class balance in the effect modifier.\n\n\\paragraph{Diagnostic rule.}\nA logistic regression over all 368 semi-real experiment--budget cells (dependent variable: HB EC-HTE $<$ Global RMSE) identifies two sufficient statistics: the worst-subgroup confusion matrix condition number $\\kappa(\\hat{M}_s) \\leq 1.25$ and the effective minority-class expert count $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$.\nWhen both conditions hold, HB outperforms global in 93.3\\% of cells; when either is violated, global is preferred in 94.7\\% of cells.\nBoth exp-015 ($\\kappa = 2.38$, effective $n = 2.5$) and exp-016 ($\\kappa = 1.55$, effective $n = 2.5$) violate both conditions, and the diagnostic correctly predicts 100\\% of their failure cells.\nSubgroup-average metrics can mask cell-level heterogeneity: in exp-015, HB EC-HTE substantially reduces bias for the three well-classified subgroups (S1--S3) but amplifies variance in the near-degenerate subgroup (S0, FNR $= 0.526$), and the S0 penalty dominates the aggregate RMSE.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/applicability_frontier.pdf}\n\\caption{Applicability frontier of EC-HTE. Green region: EC-HTE reduces bias vs.\\ global correction. Yellow: comparable performance. Red: EC-HTE underperforms. Dashed lines mark the expert budget threshold ($n_{\\text{expert}}/K = 25$) and classifier quality threshold (worst-subgroup error rate $= 0.5$). Red diamonds show semi-real experiments with actual GPT-4.1 and GPT-3.5-Turbo confusion matrices.}\n\\label{fig:applicability}\n\\end{figure}\n\n\\section{Robustness: Estimator Choice and Treatment Effect Specification}\n\\label{app:rlearner}\n\nWe verify that EC-HTE's corrected pseudo-outcomes are compatible with downstream estimators beyond CausalForest by replacing it with the R-learner~\\citep{nie2021quasi}.\nThe experiment uses $K{=}2$, extreme heterogeneity, $n_{\\text{expert}} = 500$, and 50 MC seeds; the R-learner uses 5-fold cross-fitting with gradient-boosted trees as the base learner.\n\n\\begin{table}[t]\n\\centering\n\\caption{R-learner vs.\\ CausalForest with EC-HTE correction ($K{=}2$, extreme, $n{=}500$). $|\\text{Bias}|$ and RMSE averaged over subgroups, $z$-levels, and seeds.}\n\\label{tab:rlearner}\n\\small\n\\begin{tabular}{llccc}\n\\toprule\nEstimator & Correction & $|\\text{Bias}|$ & RMSE & Cov. \\\\\n\\midrule\n\\multirow{4}{*}{R-learner}\n & Oracle & 0.006 & 0.056 & 0.94 \\\\\n & Naive & 0.121 & 0.139 & 0.47 \\\\\n & Global & 0.098 & 0.123 & 0.72 \\\\\n & EC-HTE & \\textbf{0.013} & 0.080 & 0.92 \\\\\n\\midrule\n\\multirow{2}{*}{CausalForest}\n & Naive & 0.058 & 0.090 & 0.82 \\\\\n & EC-HTE & \\textbf{0.011} & 0.093 & 0.95 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nEC-HTE reduces R-learner $|\\text{bias}|$ by 89\\% (0.121 $\\to$ 0.013) and restores coverage from 0.47 to 0.92 (Table~\\ref{tab:rlearner}).\nThe bias reduction and coverage gains are comparable to those achieved with CausalForest, confirming that EC-HTE functions as an estimator-agnostic upstream correction.\n\n\\paragraph{Multiplicative treatment effects.}\nWe further test robustness to the functional form of treatment effects by replacing the additive DGP with a multiplicative specification: $Y(1) = Y(0) \\times \\exp(\\tau(Z))$, using $K{=}2$, extreme heterogeneity, $n_{\\text{expert}} = 500$, and 50 MC seeds.\n\n\\begin{table}[t]\n\\centering\n\\caption{Multiplicative DGP results ($K{=}2$, extreme, $n{=}500$, 50 seeds). EC-HTE achieves comparable bias reduction and nominal coverage under non-additive treatment effects.}\n\\label{tab:multiplicative}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nMethod & $|\\text{Bias}|$ & RMSE & Cov. \\\\\n\\midrule\nOracle & 0.003 & 0.038 & 0.96 \\\\\nNaive & 0.135 & 0.142 & 0.44 \\\\\nGlobal & 0.110 & 0.124 & 0.54 \\\\\nEC-HTE & \\textbf{0.054} & 0.068 & 0.955 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nEC-HTE reduces RMSE by 52\\% relative to naive (0.068 vs.\\ 0.142) and restores coverage to the nominal level (0.955; Table~\\ref{tab:multiplicative}).\nEC-HTE's bias correction operates at the confusion matrix level, independent of the downstream CATE estimator and functional form of treatment effects.\n\n\\section{Robustness to Class Imbalance}\n\\label{app:classimbalance}\n\nAssumption (A3) requires $P(Z{=}1) = 0.5$, but real-world effect modifiers are often imbalanced.\nWe sweep $P(Z{=}1) \\in \\{0.1, 0.2, 0.3, 0.4, 0.5\\}$ with $K \\in \\{2,4\\}$, extreme misclassification heterogeneity, $n_{\\text{expert}}{=}250$, and 100 MC seeds (Table~\\ref{tab:pz1_sweep}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Robustness to class imbalance ($n_{\\text{expert}}{=}250$, extreme heterogeneity). R$^2$: Theorem~\\ref{thm:bias_identity} fit. Ratio: HB/Global RMSE ($<1$ = HB wins). Cov.: HB EC-HTE 95\\% CI coverage.}\n\\label{tab:pz1_sweep}\n\\small\n\\begin{tabular}{cc ccc}\n\\toprule\n$P(Z{=}1)$ & $K$ & R$^2$ & Ratio & Cov. \\\\\n\\midrule\n0.1 & 2 & 0.998 & 0.92 & 0.94 \\\\\n0.2 & 2 & 0.989 & 0.76 & 0.94 \\\\\n0.3 & 2 & 0.994 & 0.78 & 0.94 \\\\\n0.4 & 2 & 0.995 & 0.87 & 0.94 \\\\\n0.5 & 2 & 0.995 & 0.86 & 0.93 \\\\\n\\midrule\n0.1 & 4 & 0.984 & 1.54 & 0.92 \\\\\n0.2 & 4 & 0.976 & 1.68 & 0.93 \\\\\n0.3 & 4 & 0.985 & 1.12 & 0.92 \\\\\n0.4 & 4 & 0.984 & 1.08 & 0.93 \\\\\n0.5 & 4 & 0.992 & 1.06 & 0.92 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTheorem~\\ref{thm:bias_identity}'s product form remains accurate across all imbalance levels: $R^2 \\geq 0.976$ even at $P(Z{=}1) = 0.1$, confirming that the bias identity derives from confusion matrix structure rather than class balance.\nFor $K{=}2$, EC-HTE outperforms global correction at all $P(Z{=}1)$ levels (RMSE ratio 0.76--0.92), degrading gracefully under severe imbalance.\nFor $K{=}4$, EC-HTE underperforms global at $n_{\\text{expert}}{=}250$ (ratio 1.06--1.68), consistent with the budget threshold $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$: at $P(Z{=}1){=}0.1$, $K{=}4$, each subgroup receives only ${\\sim}6$ minority-class labels.\nThe gap narrows as $P(Z{=}1)$ increases (1.54 $\\to$ 1.06), and coverage remains stable at 0.92--0.94 across all configurations.\n",
      "numLines": 670,
      "startLine": 1,
      "totalLines": 670
    }
  },
  "sourceToolAssistantUUID": "823daf34-e330-417c-8162-43e1d11ad59e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-21T18:45:58.757Z_

<details open><summary>🔧 Tool call — Bash · `toolu_0152vKjdDpVJhQ8ACfEevNWb`</summary>

```json
{
  "command": "ls /home/ubuntu/ec_hte_llm_annotation/artifacts/ 2>/dev/null || echo \"NO_ARTIFACTS_DIR\"",
  "description": "Check if artifacts directory exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "445d9492-e477-4ccf-b142-412a71e99bef",
  "isSidechain": false,
  "requestId": "req_011CbGDA33EA5xUM2Z6KW8ca",
  "type": "assistant",
  "uuid": "263738c7-6514-40ee-8054-26f616b46412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TCBb6AsTBAbtGNgFMjoTLP",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12988,
      "cache_read_input_tokens": 11841,
      "output_tokens": 285,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12988,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 285,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12988,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12988
          },
          "type": "message"
        }
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

_source line 14_

```json
{
  "type": "last-prompt",
  "leafUuid": "263738c7-6514-40ee-8054-26f616b46412",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d"
}
```

---

### Runtime record

_source line 15_

```json
{
  "type": "ai-title",
  "aiTitle": "Prepare Multi-LLM validation paper template",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d"
}
```

---

### Tool result

_source line 16 · 2026-05-21T18:45:58.947Z_

<details><summary>↩ Tool result · `toolu_0152vKjdDpVJhQ8ACfEevNWb`</summary>

```text
balanced_z_annotation
diagnostic_revision
exp-008
failure_analysis
figures
kappa_sweep
mc_se_analysis
paper
pz1_sweep
seeds_100
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "263738c7-6514-40ee-8054-26f616b46412",
  "isSidechain": false,
  "promptId": "500ceecd-d23e-42ba-9539-45d70198290e",
  "type": "user",
  "uuid": "c45dd7a8-6eb4-4861-a086-3c2faee4469a",
  "toolUseResult": {
    "stdout": "balanced_z_annotation\ndiagnostic_revision\nexp-008\nfailure_analysis\nfigures\nkappa_sweep\nmc_se_analysis\npaper\npz1_sweep\nseeds_100",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "263738c7-6514-40ee-8054-26f616b46412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 17 · 2026-05-21T18:46:07.908Z_

<details><summary>Logged reasoning block</summary>

```text
Good, I've read both files. The artifacts directory exists and has contents. Now let me create the integration template file. Let me note the key style patterns from the existing paper:

1. Tables use `\small`, `\centering`
2. Caption style: descriptive with methodological notes
3. `\toprule`, `\midrule`, `\bottomrule` (booktabs)
4. Column headers with math mode
5. `\textbf{}` for bold best results
6. Consistent use of `$K{=}$`, `$N{=}$` notation
7. `\multirow` for grouped rows


8. Appendix tables use `table*` for wide ones

Now I'll create the template, matching the existing style closely.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c45dd7a8-6eb4-4861-a086-3c2faee4469a",
  "isSidechain": false,
  "requestId": "req_011CbGDAQnS2GBJ4oQhZr5Gs",
  "type": "assistant",
  "uuid": "82d4d2a2-fb45-4587-810e-b1727b8ceb17",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RpsqV7pfB2T1Zkoik83rFH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21640,
      "cache_read_input_tokens": 24829,
      "output_tokens": 2611,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2611,
          "cache_read_input_tokens": 24829,
          "cache_creation_input_tokens": 21640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21640
          },
          "type": "message"
        }
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

_source line 18 · 2026-05-21T18:46:07.915Z_

Now I have the full picture of the paper's style. Let me create the template.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "82d4d2a2-fb45-4587-810e-b1727b8ceb17",
  "isSidechain": false,
  "requestId": "req_011CbGDAQnS2GBJ4oQhZr5Gs",
  "type": "assistant",
  "uuid": "6c31e034-76c5-4a30-877f-3d5e70cb74cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RpsqV7pfB2T1Zkoik83rFH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21640,
      "cache_read_input_tokens": 24829,
      "output_tokens": 2611,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2611,
          "cache_read_input_tokens": 24829,
          "cache_creation_input_tokens": 21640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21640
          },
          "type": "message"
        }
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

_source line 19 · 2026-05-21T18:46:38.562Z_

<details open><summary>🔧 Tool call — Write · `toolu_017MCtq8iGcCSajPhDBqX81S`</summary>

```json
{
  "file_path": "/home/ubuntu/ec_hte_llm_annotation/artifacts/c1_integration_template.tex",
  "content": "% =============================================================================\n% C1 Multi-LLM Validation — Integration Template\n% Insert into experiments.tex (after Section 5.6 PPCI) and appendix.tex\n% Replace [TBD] placeholders with GPU experiment results\n% =============================================================================\n\n% ─────────────────────────────────────────────────────────────────────────────\n% PART 1: Main text subsection (experiments.tex, after \\subsection{PPCI...})\n% ─────────────────────────────────────────────────────────────────────────────\n\n\\subsection{Multi-LLM Validation}\n\\label{sec:multi_llm}\n\nTo validate EC-HTE beyond a single annotator model, we apply four open-source LLMs---Llama-3.1-8B-Instruct, Qwen2.5-7B-Instruct, Mistral-7B-Instruct-v0.3, and Gemma-2-9B-IT---to the TweetEval sentiment task with a balanced subgroup definition ($P(Z{=}1) \\approx \\text{[TBD]}$).\nTable~\\ref{tab:multi_llm} summarizes the per-model misclassification profiles and correction performance.\n\n% [TBD: 1-2 sentences on key finding — e.g., EC-HTE improves over global in X/4 models where kappa(M_hat) < threshold]\n\n% [TBD: 1 sentence on which models satisfy the Prop 2 diagnostic condition]\n\n% [TBD: 1 sentence connecting to applicability conditions from Section~\\ref{sec:budget}]\n\n\\begin{table}[t]\n\\centering\n\\caption{Multi-LLM validation on TweetEval sentiment ($N{=}500$, balanced $Z$). $\\kappa(\\hat{M})$: worst-subgroup confusion matrix condition number. Bold marks lowest RMSE per row. [TBD: complete caption with key takeaway]}\n\\label{tab:multi_llm}\n\\small\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & $P(Z{=}1)$ & $\\kappa(\\hat{M})$ & eff.\\ $n$ & RMSE\\textsubscript{naive} & RMSE\\textsubscript{global} & RMSE\\textsubscript{EC-HTE} \\\\\n\\midrule\nLlama-3.1-8B & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nQwen2.5-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nMistral-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nGemma-2-9B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n% ─────────────────────────────────────────────────────────────────────────────\n% PART 2: Appendix detailed results (appendix.tex, new section)\n% ─────────────────────────────────────────────────────────────────────────────\n\n\\section{Multi-LLM Detailed Results}\n\\label{app:multi_llm}\n\nTable~\\ref{tab:multi_llm_detail} reports per-subgroup misclassification profiles for four open-source LLMs.\n% [TBD: 1 sentence on cross-model consistency of subgroup error structure]\n% [TBD: 1 sentence on which subgroup(s) exhibit the highest/lowest error rates across models]\n\n\\begin{table*}[t]\n\\centering\n\\caption{Per-subgroup misclassification profiles for four open-source LLMs on TweetEval sentiment ($Z{=}0$: negative, $Z{=}1$: neutral+positive). $\\pi_s$: symmetric misclassification rate; $\\kappa(\\hat{M}_s)$: per-subgroup condition number.}\n\\label{tab:multi_llm_detail}\n\\small\n\\begin{tabular}{llcccccc}\n\\toprule\nModel & $Z$ & $n$ & Accuracy & FPR & FNR & $\\pi_s$ & $\\kappa(\\hat{M}_s)$ \\\\\n\\midrule\n\\multirow{2}{*}{Llama-3.1-8B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{2}{*}{Qwen2.5-7B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{2}{*}{Mistral-7B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{2}{*}{Gemma-2-9B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n% --- Optional: per-model correction results (full breakdown) ---\n\n\\begin{table*}[t]\n\\centering\n\\caption{Per-model correction performance on TweetEval ($N{=}500$, balanced $Z$, [TBD] MC seeds). $|\\text{Bias}|$ and RMSE averaged over subgroups and $z$-levels. Bold marks lowest $|\\text{bias}|$ per model.}\n\\label{tab:multi_llm_correction}\n\\small\n\\begin{tabular}{ll ccc}\n\\toprule\nModel & Method & $|\\text{Bias}|$ & RMSE & Cov. \\\\\n\\midrule\n\\multirow{3}{*}{Llama-3.1-8B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{3}{*}{Qwen2.5-7B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{3}{*}{Mistral-7B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{3}{*}{Gemma-2-9B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n% --- Optional: Diagnostic condition summary ---\n\n\\paragraph{Diagnostic criterion.}\n% [TBD: For each model, report whether the Prop 2 condition is satisfied and for which subgroups]\n% [TBD: Connect to applicability frontier (Figure~\\ref{fig:applicability})]\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6c31e034-76c5-4a30-877f-3d5e70cb74cf",
  "isSidechain": false,
  "requestId": "req_011CbGDAQnS2GBJ4oQhZr5Gs",
  "type": "assistant",
  "uuid": "df911179-e449-40a2-9b86-4046b0b42873",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RpsqV7pfB2T1Zkoik83rFH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21640,
      "cache_read_input_tokens": 24829,
      "output_tokens": 2611,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2611,
          "cache_read_input_tokens": 24829,
          "cache_creation_input_tokens": 21640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21640
          },
          "type": "message"
        }
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

_source line 20 · 2026-05-21T18:46:38.580Z_

<details><summary>↩ Tool result · `toolu_017MCtq8iGcCSajPhDBqX81S`</summary>

```text
File created successfully at: /home/ubuntu/ec_hte_llm_annotation/artifacts/c1_integration_template.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "df911179-e449-40a2-9b86-4046b0b42873",
  "isSidechain": false,
  "promptId": "500ceecd-d23e-42ba-9539-45d70198290e",
  "type": "user",
  "uuid": "17e22ad9-449d-4fb1-b68e-1c303d6dc5b8",
  "toolUseResult": {
    "type": "create",
    "filePath": "/home/ubuntu/ec_hte_llm_annotation/artifacts/c1_integration_template.tex",
    "content": "% =============================================================================\n% C1 Multi-LLM Validation — Integration Template\n% Insert into experiments.tex (after Section 5.6 PPCI) and appendix.tex\n% Replace [TBD] placeholders with GPU experiment results\n% =============================================================================\n\n% ─────────────────────────────────────────────────────────────────────────────\n% PART 1: Main text subsection (experiments.tex, after \\subsection{PPCI...})\n% ─────────────────────────────────────────────────────────────────────────────\n\n\\subsection{Multi-LLM Validation}\n\\label{sec:multi_llm}\n\nTo validate EC-HTE beyond a single annotator model, we apply four open-source LLMs---Llama-3.1-8B-Instruct, Qwen2.5-7B-Instruct, Mistral-7B-Instruct-v0.3, and Gemma-2-9B-IT---to the TweetEval sentiment task with a balanced subgroup definition ($P(Z{=}1) \\approx \\text{[TBD]}$).\nTable~\\ref{tab:multi_llm} summarizes the per-model misclassification profiles and correction performance.\n\n% [TBD: 1-2 sentences on key finding — e.g., EC-HTE improves over global in X/4 models where kappa(M_hat) < threshold]\n\n% [TBD: 1 sentence on which models satisfy the Prop 2 diagnostic condition]\n\n% [TBD: 1 sentence connecting to applicability conditions from Section~\\ref{sec:budget}]\n\n\\begin{table}[t]\n\\centering\n\\caption{Multi-LLM validation on TweetEval sentiment ($N{=}500$, balanced $Z$). $\\kappa(\\hat{M})$: worst-subgroup confusion matrix condition number. Bold marks lowest RMSE per row. [TBD: complete caption with key takeaway]}\n\\label{tab:multi_llm}\n\\small\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & $P(Z{=}1)$ & $\\kappa(\\hat{M})$ & eff.\\ $n$ & RMSE\\textsubscript{naive} & RMSE\\textsubscript{global} & RMSE\\textsubscript{EC-HTE} \\\\\n\\midrule\nLlama-3.1-8B & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nQwen2.5-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nMistral-7B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\nGemma-2-9B   & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n% ─────────────────────────────────────────────────────────────────────────────\n% PART 2: Appendix detailed results (appendix.tex, new section)\n% ─────────────────────────────────────────────────────────────────────────────\n\n\\section{Multi-LLM Detailed Results}\n\\label{app:multi_llm}\n\nTable~\\ref{tab:multi_llm_detail} reports per-subgroup misclassification profiles for four open-source LLMs.\n% [TBD: 1 sentence on cross-model consistency of subgroup error structure]\n% [TBD: 1 sentence on which subgroup(s) exhibit the highest/lowest error rates across models]\n\n\\begin{table*}[t]\n\\centering\n\\caption{Per-subgroup misclassification profiles for four open-source LLMs on TweetEval sentiment ($Z{=}0$: negative, $Z{=}1$: neutral+positive). $\\pi_s$: symmetric misclassification rate; $\\kappa(\\hat{M}_s)$: per-subgroup condition number.}\n\\label{tab:multi_llm_detail}\n\\small\n\\begin{tabular}{llcccccc}\n\\toprule\nModel & $Z$ & $n$ & Accuracy & FPR & FNR & $\\pi_s$ & $\\kappa(\\hat{M}_s)$ \\\\\n\\midrule\n\\multirow{2}{*}{Llama-3.1-8B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{2}{*}{Qwen2.5-7B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{2}{*}{Mistral-7B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{2}{*}{Gemma-2-9B}\n & $Z{=}0$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n & $Z{=}1$ & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n% --- Optional: per-model correction results (full breakdown) ---\n\n\\begin{table*}[t]\n\\centering\n\\caption{Per-model correction performance on TweetEval ($N{=}500$, balanced $Z$, [TBD] MC seeds). $|\\text{Bias}|$ and RMSE averaged over subgroups and $z$-levels. Bold marks lowest $|\\text{bias}|$ per model.}\n\\label{tab:multi_llm_correction}\n\\small\n\\begin{tabular}{ll ccc}\n\\toprule\nModel & Method & $|\\text{Bias}|$ & RMSE & Cov. \\\\\n\\midrule\n\\multirow{3}{*}{Llama-3.1-8B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{3}{*}{Qwen2.5-7B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{3}{*}{Mistral-7B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\midrule\n\\multirow{3}{*}{Gemma-2-9B}\n & Naive  & [TBD] & [TBD] & [TBD] \\\\\n & Global & [TBD] & [TBD] & [TBD] \\\\\n & HB EC-HTE & [TBD] & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n% --- Optional: Diagnostic condition summary ---\n\n\\paragraph{Diagnostic criterion.}\n% [TBD: For each model, report whether the Prop 2 condition is satisfied and for which subgroups]\n% [TBD: Connect to applicability frontier (Figure~\\ref{fig:applicability})]\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  },
  "sourceToolAssistantUUID": "df911179-e449-40a2-9b86-4046b0b42873",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-21T18:46:45.484Z_

文件已创建：`/home/ubuntu/ec_hte_llm_annotation/artifacts/c1_integration_template.tex`

包含三部分：
1. **主文 subsection**（插入 experiments.tex 的 PPCI 之后）— 叙述框架 + 摘要表 `tab:multi_llm`
2. **Appendix 详细表** — per-subgroup 混淆矩阵指标 `tab:multi_llm_detail` + per-model 完整校正结果 `tab:multi_llm_correction`
3. **Diagnostic paragraph** — Prop 2 条件的占位框架

风格已对齐现有论文：booktabs、`\small`、`$K{=}$` 记法、`\textbf` 标注最优值、caption 含方法论说明。所有待填数字标记为 `[TBD]`。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "17e22ad9-449d-4fb1-b68e-1c303d6dc5b8",
  "isSidechain": false,
  "requestId": "req_011CbGDDL8DxG8SFRWHNHtSf",
  "type": "assistant",
  "uuid": "cfa1b2ee-84e3-4ad5-82cb-df5cc1b0bbce",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VJiiRAgJYfuC6mqQtH9iqL",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2653,
      "cache_read_input_tokens": 46469,
      "output_tokens": 247,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2653,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 247,
          "cache_read_input_tokens": 46469,
          "cache_creation_input_tokens": 2653,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2653
          },
          "type": "message"
        }
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

_source line 22_

```json
{
  "type": "last-prompt",
  "leafUuid": "cfa1b2ee-84e3-4ad5-82cb-df5cc1b0bbce",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d"
}
```

---

### Runtime record

_source line 23_

```json
{
  "type": "ai-title",
  "aiTitle": "Prepare Multi-LLM validation paper template",
  "sessionId": "057f7a49-0f58-488c-b692-f259d0d8706d"
}
```

---

# Research conversation: <project_context> # 项目: turn_residual_gating ## 运行环境 - 服务器名: westd-20861 - SSH 连接命令: ssh connect.westd.seetacloud.com # 

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 27
- **Recorded user turns:** 1
- **Tool calls:** 5
- **Original source:** `logs/chats/exported-trajectories/account-1/42862026-8466-421c-acf7-d5e4934cde8c.jsonl`
- **Structured JSON:** [`4dc6cd4ee497996125fc.json`](../../sessions/4d/4dc6cd4ee497996125fc.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-22T16:07:09.157Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-22T16:07:09.157Z",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "content": "&lt;project_context>\n# 项目: turn_residual_gating\n\n## 运行环境\n- 服务器名: westd-20861\n- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/turn_residual_gating\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n**扩展 Appendix B 的 loss iteration 表（Table 2），加一列 \"Failure Mechanism\"。**\n\n**先 Read 以下文件：**\n1. `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex` — 找到 Table 2 (loss iterations)\n2. `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper_framing.md` — 找 loss iteration 的失败原因描述\n\n## 背景\n\n论文有 Table 2 列出了 v1-v7 的 7 种 loss 配置和结果。需要新增一列 \"Failure Mechanism\"，用一句话说明每种 loss 为何失败/成功。\n\n## 各 loss 的失败机制（从实验记录中提取）\n\n| Version | Loss Family | Failure Mechanism |\n|---------|------------|-------------------|\n| v1 | Hinge (threshold) | GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium |\n| v2 | Cumulative GAR | Numerical instability from cumulative product; ε-stabilization insufficient |\n| v3 | Maximize (-mean GAR) | Unbounded reward drives gates toward identity (all-pass); no layer selectivity |\n| v3b | Maximize + high λ | Same identity collapse as v3, higher λ only accelerates convergence to degenerate solution |\n| v5 | Maximize + rebalanced | Same structural flaw; rebalancing hyperparameters delays but does not prevent identity collapse |\n| v6 | Smooth saturation (-target·tanh) | Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory |\n| v7 | MSE bilateral + gate diversity | **Converges**: bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity |\n\n## 任务\n\n1. 在 appendix.tex 中找到 Table 2（tab:loss-iterations 或类似 label）\n2. 在表格中新增一列 \"Failure Mechanism\"\n3. 每个 loss 填入上述一句话描述\n4. v7 (MSE) 行标记为成功（可用 \\checkmark 或 bold）\n5. 调整表格宽度（可能需要改为 table* 或用 \\small/\\scriptsize + adjustbox）\n6. 确保 LaTeX 语法正确\n\n**只修改 Table 2 相关部分，不要改其他内容。**\n\n文件路径：`/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex`"
}
```

---

### Runtime record

_source line 2 · 2026-05-22T16:07:09.161Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-22T16:07:09.161Z",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

## Round 1

25 recorded events

### User

_source line 3 · 2026-05-22T16:07:09.201Z_

&lt;project_context>
# 项目: turn_residual_gating

## 运行环境
- 服务器名: westd-20861
- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/turn_residual_gating


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
**扩展 Appendix B 的 loss iteration 表（Table 2），加一列 "Failure Mechanism"。**

**先 Read 以下文件：**
1. `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex` — 找到 Table 2 (loss iterations)
2. `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper_framing.md` — 找 loss iteration 的失败原因描述

## 背景

论文有 Table 2 列出了 v1-v7 的 7 种 loss 配置和结果。需要新增一列 "Failure Mechanism"，用一句话说明每种 loss 为何失败/成功。

## 各 loss 的失败机制（从实验记录中提取）

| Version | Loss Family | Failure Mechanism |
|---------|------------|-------------------|
| v1 | Hinge (threshold) | GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium |
| v2 | Cumulative GAR | Numerical instability from cumulative product; ε-stabilization insufficient |
| v3 | Maximize (-mean GAR) | Unbounded reward drives gates toward identity (all-pass); no layer selectivity |
| v3b | Maximize + high λ | Same identity collapse as v3, higher λ only accelerates convergence to degenerate solution |
| v5 | Maximize + rebalanced | Same structural flaw; rebalancing hyperparameters delays but does not prevent identity collapse |
| v6 | Smooth saturation (-target·tanh) | Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory |
| v7 | MSE bilateral + gate diversity | **Converges**: bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity |

## 任务

1. 在 appendix.tex 中找到 Table 2（tab:loss-iterations 或类似 label）
2. 在表格中新增一列 "Failure Mechanism"
3. 每个 loss 填入上述一句话描述
4. v7 (MSE) 行标记为成功（可用 \checkmark 或 bold）
5. 调整表格宽度（可能需要改为 table* 或用 \small/\scriptsize + adjustbox）
6. 确保 LaTeX 语法正确

**只修改 Table 2 相关部分，不要改其他内容。**

文件路径：`/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "ccea817f-9102-4fb3-b34e-f643df40ae8c",
  "type": "user",
  "uuid": "7ab446a3-803e-46a1-9aaf-2489c81784ce",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-22T16:07:09.200Z_

```json
{
  "parentUuid": "7ab446a3-803e-46a1-9aaf-2489c81784ce",
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
  "uuid": "d16b6013-3b5f-4033-8f80-0d9405b6f90d",
  "timestamp": "2026-05-22T16:07:09.200Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-22T16:07:09.200Z_

```json
{
  "parentUuid": "d16b6013-3b5f-4033-8f80-0d9405b6f90d",
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
  "uuid": "6eaa5127-262d-487d-8976-16d333e9184a",
  "timestamp": "2026-05-22T16:07:09.200Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 6 · 2026-05-22T16:07:09.200Z_

```json
{
  "parentUuid": "6eaa5127-262d-487d-8976-16d333e9184a",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "46ca89b6-3343-4ac9-909b-3aa5fa28ab1a",
  "timestamp": "2026-05-22T16:07:09.200Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
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
  "aiTitle": "Extend Table 2 with failure mechanism column",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

### Assistant

_source line 8 · 2026-05-22T16:07:13.085Z_

Reading the two files to understand the current table structure and context.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "46ca89b6-3343-4ac9-909b-3aa5fa28ab1a",
  "isSidechain": false,
  "requestId": "req_011CbHtrr677z2AQaXeHnivM",
  "type": "assistant",
  "uuid": "0e9aebe2-84a7-4153-ad76-c5892dba1138",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017pRD53BtqaPxdw5hSruSfC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13291,
      "cache_read_input_tokens": 11841,
      "output_tokens": 176,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13291,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 176,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13291,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13291
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-22T16:07:21.901Z_

<details open><summary>🔧 Tool call — Read · `toolu_011zLJrSX8fU6nkny5MzeUJR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0e9aebe2-84a7-4153-ad76-c5892dba1138",
  "isSidechain": false,
  "requestId": "req_011CbHtrr677z2AQaXeHnivM",
  "type": "assistant",
  "uuid": "16496c89-458a-4ccf-9979-65a4accebaef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017pRD53BtqaPxdw5hSruSfC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13291,
      "cache_read_input_tokens": 11841,
      "output_tokens": 176,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13291,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 176,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13291,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13291
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-22T16:07:21.916Z_

<details><summary>↩ Tool result · `toolu_011zLJrSX8fU6nkny5MzeUJR`</summary>

```text
1	\section{Training Hyperparameters}\label{sec:appendix-hyper}
2	
3	All fine-tuned variants share the following configuration: Qwen-2.5-7B-Instruct base model, LoRA rank 16 ($\alpha$=32) on \texttt{q\_proj} and \texttt{v\_proj}, AdamW optimizer (lr = $2 \times 10^{-4}$, $\beta_1$=0.9, $\beta_2$=0.999), batch size 1 with gradient accumulation 8, 3 epochs over 8K UltraChat conversations, maximum sequence length 2048, seed 42. ThreadGate gates use a 10$\times$ learning rate multiplier and initial bias 1.5 ($\sigma(1.5) \approx 0.82$).
4	
5	\section{Loss Formulation Search}\label{sec:appendix-loss}
6	
7	Table~\ref{tab:loss-iterations} summarizes the seven loss configurations explored before arriving at the final MSE + gate diversity formulation (\S\ref{sec:loss}). Configurations v1--v6 span three alternative loss families; none converged during training.
8	
9	\begin{table}[h]
10	\centering\small
11	\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}
12	\label{tab:loss-iterations}
13	\begin{tabular}{l l l c c}
14	\toprule
15	 & \textbf{Loss Family} & \textbf{Status} & \textbf{GAR} & \textbf{PPL} \\
16	\midrule
17	v1  & Cumulative            & \texttimes~GAR loss $\to$ 0     & ---  & ---  \\
18	v2  & Cumulative + $\varepsilon$ & \texttimes~same trajectory & ---  & ---  \\
19	v3  & Maximize ($\lambda$=2)  & \texttimes~gate frozen        & ---  & ---  \\
20	v3b & Maximize ($\lambda$=10) & \texttimes~identity collapse   & ---  & ---  \\
21	v5  & Maximize ($\lambda$=1)  & \texttimes~identity collapse   & ---  & ---  \\
22	v6  & Smooth saturation       & \texttimes~identity collapse   & ---  & ---  \\
23	v7  & MSE + gate div          & \checkmark~converged           & 0.50 & 2.78 \\
24	\bottomrule
25	\end{tabular}
26	\end{table}
27	
28	\section{Instruction Retention Details}\label{sec:appendix-ir}
29	
30	Across 18 system-prompt constraint types, $\beta$\,=\,3 steering increases content constraint compliance by +23.8\,pp (GAR-compliance $r$\,=\,0.200, $p$\,=\,0.007; McNemar $p$\,=\,0.077), providing exploratory evidence for downstream benefit pending multi-model confirmation.
31	
32	Maximize-family losses ($-\text{mean}(\text{GAR})$) consistently drove gates toward identity: the unbounded objective rewards full pass-through ($g \to 1.0$), collapsing gate diversity (std $<$ 0.025). Bounded variants (smooth saturation) decelerated but did not prevent this collapse, motivating the MSE formulation targeting a finite GAR level.
33	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "16496c89-458a-4ccf-9979-65a4accebaef",
  "isSidechain": false,
  "promptId": "ccea817f-9102-4fb3-b34e-f643df40ae8c",
  "type": "user",
  "uuid": "cfd621f3-6349-40c5-9554-1a79ba6be0d5",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
      "content": "\\section{Training Hyperparameters}\\label{sec:appendix-hyper}\n\nAll fine-tuned variants share the following configuration: Qwen-2.5-7B-Instruct base model, LoRA rank 16 ($\\alpha$=32) on \\texttt{q\\_proj} and \\texttt{v\\_proj}, AdamW optimizer (lr = $2 \\times 10^{-4}$, $\\beta_1$=0.9, $\\beta_2$=0.999), batch size 1 with gradient accumulation 8, 3 epochs over 8K UltraChat conversations, maximum sequence length 2048, seed 42. ThreadGate gates use a 10$\\times$ learning rate multiplier and initial bias 1.5 ($\\sigma(1.5) \\approx 0.82$).\n\n\\section{Loss Formulation Search}\\label{sec:appendix-loss}\n\nTable~\\ref{tab:loss-iterations} summarizes the seven loss configurations explored before arriving at the final MSE + gate diversity formulation (\\S\\ref{sec:loss}). Configurations v1--v6 span three alternative loss families; none converged during training.\n\n\\begin{table}[h]\n\\centering\\small\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Instruction Retention Details}\\label{sec:appendix-ir}\n\nAcross 18 system-prompt constraint types, $\\beta$\\,=\\,3 steering increases content constraint compliance by +23.8\\,pp (GAR-compliance $r$\\,=\\,0.200, $p$\\,=\\,0.007; McNemar $p$\\,=\\,0.077), providing exploratory evidence for downstream benefit pending multi-model confirmation.\n\nMaximize-family losses ($-\\text{mean}(\\text{GAR})$) consistently drove gates toward identity: the unbounded objective rewards full pass-through ($g \\to 1.0$), collapsing gate diversity (std $<$ 0.025). Bounded variants (smooth saturation) decelerated but did not prevent this collapse, motivating the MSE formulation targeting a finite GAR level.\n",
      "numLines": 33,
      "startLine": 1,
      "totalLines": 33
    }
  },
  "sourceToolAssistantUUID": "16496c89-458a-4ccf-9979-65a4accebaef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-22T16:07:27.388Z_

<details><summary>↩ Tool result · `toolu_01Fo1mhyFQbnNaaBVk1Kkbub`</summary>

```text
1	# Paper Framing: Mechanistic Analysis of Training-Inference Distribution Shift in Attention Steering
2	
3	> 定位: **Mechanistic insight paper**（不是简单 negative result）。核心卖点是 teacher-forcing→generation 分布偏移如何摧毁 lightweight residual gating 的 auxiliary attention loss 泛化性（~30× 断层的定量证据）。这个 insight 为 auxiliary attention loss 在 teacher-forcing 下的 exposure bias 脆弱性提供首个实证刻画。
4	> Novelty 排序: (1) exposure bias 对 auxiliary attention loss 泛化性的首个实证刻画 (~30× gap) > (2) PCGrad 因果排除梯度方向冲突 + "观察→假设→排除→指向真因" 完整因果链 (D028) > (3) principled intervention + systematic ablation 的 negative result
5	> **⚠️ Dream review D024: "Cannot" overclaims, novelty "first measurement" 过高, 缺 gradient surgery baseline (PCGrad). 标题改 "Fails to", novelty 降级 "first empirical characterization"**
6	> 目标会议: EMNLP 2026, ARR August cycle, deadline 2026-08-03 (~10.5 weeks)
7	> 最后更新: 2026-05-22 (C5 fully confirmed; gap numbers unified to ~30×; M017 修正: PPL -46% 为跨协议伪影, IID PPL 无差异; selective dissociation 撤回; D033 跨变体确认)
8	> **⚠️ Llama-3 跨模型验证 = MUST-HAVE**（不含 → Findings 3.0 紧绷；含 → 3.0-3.5）
9	
10	---
11	
12	## 1. Title Candidates
13	
14	- **T1 (推荐)**: Why Lightweight Gating Fails to Fix Multi-Turn Attention Degradation: A Mechanistic Analysis
15	- **T2**: The Distribution Shift Trap: Why Training-Time Attention Steering Fails at Inference
16	- **T3**: Residual Gating Fails to Recover Goal Attention in Multi-Turn Dialogue
17	- **T4**: Lightweight Gating Struggles with Multi-Turn Attention Degradation: Evidence from Exposure Bias
18	
19	推荐 T1: "Fails to Fix" 替代 "Cannot Fix"（审稿共识：证据仅支持 tested conditions 下的失败，非绝对否定）。"Lightweight Gating" 覆盖标量+uniform gate。
20	
21	---
22	
23	## 2. Story Arc
24	
25	Multi-turn dialogue performance in LLMs degrades as conversations grow longer. Dongre et al. (2026) quantified this through the Goal Accessibility Ratio (GAR), showing 27-48% drops over 50 turns, while their residual stream probes reveal that goal information persists (AUC up to 0.98) even as the attention channel closes. This creates a natural hypothesis: if the information is in the residual stream but attention fails to access it, a learnable gate on the residual connection should recover it. We implement this hypothesis as ThreadGate, a per-layer gating module trained with joint NTP and GAR objectives. ThreadGate successfully optimizes GAR during training (0.02 to 0.48), and this improvement transfers perfectly when evaluated on same-distribution text at inference (GAR-ours = 0.49). However, on model-generated text, GAR-ours collapses to 0.016—a ~30× gap driven by text distribution shift. Our central finding is that attention patterns learned under teacher-forced contexts (gold text) do not generalize to autoregressive generation contexts (model-generated text), the classic exposure bias phenomenon. This distribution shift is structural, independent of loss design or gating architecture. We further identify two coupled mechanisms that amplify the shift: (1) NTP loss dominates gate gradients, causing gates to learn reverse turn conditioning (suppressing at early turns where GAR is high, becoming passive at late turns where intervention is needed); (2) at inference time, gates attenuate residual updates by only 2-7%, far too weak to shift attention patterns. Four-way ablation (ThreadGate vs. Uniform Gate vs. LoRA-only vs. Base) confirms gating provides zero incremental contribution. Notably, this ~30× gap is specific to GAR-ours (last-token attention to goals); GAR-Dongre (all-token attention) shows uniformly low values regardless of text distribution, revealing that exposure bias selectively disrupts summary-position attention patterns. Combined with Dongre et al.'s independent failure of goal re-injection, our results provide the first empirical characterization of how text distribution shift (exposure bias) selectively destroys attention patterns learned through auxiliary losses, and identify the specific mechanisms through which this vulnerability manifests.
26	
27	---
28	
29	## 3. Core Claims
30	
31	| # | Claim | 支撑 | 状态 |
32	|---|-------|------|------|
33	| C1 | GAR 衰减是真实且严重的结构性现象: Qwen-2.5-7B raw GAR 下降 70.8%, normalized GAR 下降 ~21% | Phase 1 GAR 诊断 | ✅ 已验证 |
34	| C2 | Residual gating 训练时在 same-distribution text 上有效优化 GAR-ours (0.48→0.49 泛化成功)，但在 model-generated text 上完全失败 (GAR-ours=0.016, ~30× text distribution shift gap)。GAR-Dongre 在两种分布上均低（~0.01-0.016），无 gap——说明分布偏移选择性影响 summary-position attention pattern。 | v7 训练曲线 + 4-way eval + v7 直接 eval + Reviewer 独立验证 (D024) | ✅ 已验证（precision upgrade） |
35	| C3 | 失败机制的因果分析: (1) Distribution shift 是主因（D028 PCGrad 因果排除梯度方向冲突）; (2) NTP 幅度主导 gate 学习 → NF1 反向 turn conditioning; (3) NF3 gate 干预强度不足 2-7%。PCGrad ablation: 消除方向冲突后 cos_sim 围绕 0 震荡(range -0.151 to +0.091)，但 L_GAR 坍塌轨迹不变且无延迟 → 方向冲突非因果因素。**推理端确认（IID same-protocol）**: v9 GAR-ours=0.0151 vs v7=0.0157 (差<0.1pp), **v9 IID PPL=2.780 vs v7=2.784 (差0.004，无改善)**——PCGrad 消除方向冲突后所有可观测指标均 ≈ v7，方向冲突因 NTP 幅度主导而完全 inconsequential | D014 gate-profile + 梯度冲突量化 + **D028 PCGrad 因果排除** + v9 推理 eval + **M017 PPL 修正** | ✅ **End-to-end 完成**: 训练端 + 推理端均确认梯度方向冲突对 GAR 和 PPL 均无因果影响 |
36	| C4 | Gating 无增量贡献: 四路消融 LoRA-only ≈ TG ≈ UG（GAR + PPL 双指标）。IID: GAR 差异<0.6pp, PPL 均 ~2.78。**Model-gen (D033): v9 PCGrad=0.0151, UG=0.0149, LoRA-only=0.0245 均接近 baseline 0.0122——~30× gap 在所有训练变体上普遍存在，排除 gating mechanism / turn-conditioning / gradient conflict 作为因果因素** | D021 四路 eval + D033 model-gen eval | ✅ **双重验证**: IID (D021) + model-gen (D033)。model-gen regime 进一步确认 gating 零增量且 GAR collapse 是训练-推理分布偏移的普遍现象 |
37	| C5 | 跨模型验证: Llama-3.1-8B 上复现同样的失败模式 | Phase 1 ✅ (GAR decay 80.2%, D042), Phase 2 ✅ (TG gap 27× median, gating zero-increment TG≈LO, LoRA-only N=20 eval) | ✅ Fully confirmed |
38	
39	---
40	
41	## 4. Negative Findings (NF)
42	
43	| # | Finding | 证据 | 叙事角色 |
44	|---|---------|------|----------|
45	| NF1 | Gate turn conditioning 方向反转: 27/28 层 gate diff (turn1-turn21) < 0，早期 turn 强抑制，晚期 turn passive | D014 eval gate-profile | 解释 why gating fails: NTP 梯度推 gate→1.0，晚期 turn 推力最强 |
46	| NF2 | ~30× text distribution shift gap (GAR-ours): ultrachat 文本 0.49 vs 模型生成文本 0.016。Same-distribution 泛化成功（训练 0.48 → ultrachat eval 0.49），cross-distribution 泛化失败。**D033 跨变体确认**: v9 PCGrad (0.0151), UG (0.0149), LoRA-only (0.0245) model-gen GAR 均接近 baseline (0.0122)——gap 独立于训练策略，是 exposure bias 的普遍表现。GAR-Dongre 在两种分布上均低（~0.01-0.019），无 gap——分布偏移选择性影响 summary-position (last token) attention pattern | D015 + 4-way eval + v7 direct eval + D024 + **D033 cross-variant model-gen** | 核心 negative finding。精确定位为 TEXT DISTRIBUTION SHIFT（exposure bias）。D033 确认跨所有训练变体的普遍性。 |
47	| NF3 | 推理时 gate attenuation 仅 2-7% (gate_mean=0.93-0.98)，近乎 identity | D014 gate dynamic range 数据 | 解释 why 推理时 GAR 不改善: 干预强度不足 |
48	| NF4 | Eval baseline confound (Phase1 base vs Phase2 LoRA 文本不同) | P0 代码分析 | 已修正 → standard_conversations.json 统一 eval |
49	
50	---
51	
52	## 5. Key Selling Points
53	
54	**SP1 (核心卖点): Exposure bias 对 auxiliary attention loss 泛化性的首个实证刻画。** ~30× training-inference GAR-ours gap 提供了 teacher-forcing distribution shift 如何摧毁 auxiliary attention loss 泛化性的实证证据。训练时模型在 gold context 上优化 attention pattern，推理时在自身生成的 context 上条件化——两者分布不同导致 attention pattern 不迁移。虽然 exposure bias 概念本身已知 (Bengio et al. 2015)，且 sequence generation 中有量化先例 (Ranzato et al. 2016, Wiseman & Rush 2016)，但此前无人刻画其对 auxiliary attention loss 的具体影响。我们的 ~30× gap 测量展示了这种脆弱性在 attention steering 场景下的严重程度。**注意：(1) claim scope 严格限于 lightweight residual gating + GAR auxiliary loss 的实测范围，不泛化到所有 attention steering 方法。(2) ~30× gap 在 GAR-ours（last token only, summary-position attention）上测得（IID 0.50 vs model-gen 0.016）；GAR-Dongre（all response tokens）在两种分布上均低（~0.01-0.019），无 gap——表明 exposure bias 选择性影响 summary-position attention pattern，这一差异本身有分析价值。**
55	
56	**SP2: NTP-GAR 梯度动力学 + PCGrad 因果排除（gradient conflict is inconsequential）。** 观察到 67-79% 的层 NTP-GAR 梯度方向冲突（cos_sim<0）+ NTP 幅度 3-15x 压制 GAR（mag_ratio 7.5→14.7x）。**PCGrad 消融（D028）因果排除方向冲突**：投影后 cos_sim 围绕 0 震荡（range -0.151 to +0.091），L_GAR 坍塌轨迹不变。**推理端确认（IID same-protocol）**: v9 IID PPL = 2.780 vs v7 = 2.784（差 0.004，无改善）; v9 GAR-ours = 0.0151 vs v7 = 0.0157（差 <0.1pp）——**PCGrad 消除方向冲突后所有可观测指标均无变化**（GAR、PPL、NTP 均 ≈ v7）。方向冲突虽然可测量存在于 v7 中，但对训练和推理结果无任何因果影响——10-40× NTP 幅度主导使方向冲突完全无关紧要（inconsequential）。**⚠️ M017: 此前 "PPL -46%" 和 "selective dissociation" 论述为跨协议对比伪影（model-gen PPL 1.50 vs IID PPL 2.78），已撤回。** **精确 claim scope**: gradient direction conflict is **neither necessary nor sufficient** for the ~30× GAR gap; exposure bias alone is sufficient。NOT necessary: 移除冲突→gap仍在; NOT sufficient: v7有冲突但L_GAR训练时收敛; Exposure bias is sufficient: 训练≠推理分布→GAR泛化失败。**Gate 行为额外 insight**: v9 gate dynamic range 比 v7 更宽 (L15 range 0.33 vs v7 0.21)——PCGrad 给 gate 更大自由度，但 gate 用该自由度更激进地优化 NTP 而非 GAR，说明优化景观固有偏好语言建模目标。
57	
58	**SP3: Principled 设计动机 + 系统性探索。** Dongre 发现 goal info 在 residual stream 持续存在 (probe AUC=0.98)，residual gating 是最直接的架构响应。v1-v7 覆盖 4 种核心 loss 设计 across 7 training configurations，MSE+gate_div 是唯一训练收敛方案。四路消融严格隔离贡献: TG (learned gate + GAR loss) / UG (uniform gate + GAR loss) / LoRA-only (gate=1.0 fixed + GAR loss, 无 gating 机制) / Base。注意：三个 fine-tuned 变体均使用 GAR loss，消融测试的是 gating 机制的增量贡献，而非 GAR loss 本身的效果。
59	
60	**SP4: Convergent evidence with Dongre。** Dongre diagnosed the problem; we attempted the first systematic cure and uncovered fundamental limitations。两种独立干预路线（goal re-injection + residual gating）均失败，共同指向 NTP 优化压力下 attention steering 的根本困难。
61	
62	**SP5: 三阶段训练动力学。** v7 展现 plateau → phase transition → convergence 的清晰训练动力学，证明 MSE 双向 loss 设计本身是 sound 的，问题在泛化而非训练。
63	
64	---
65	
66	## 6. Anticipated Reviewer Concerns
67	
68	| # | 严重度 | 预期质疑 | 回应策略 |
69	|---|--------|----------|----------|
70	| W1 | **致命** | 单模型验证不够 | Llama-3.1-8B 跨模型验证是 **MUST-HAVE**。Qwen 完整消融 + Llama 复现。不含 Llama → Findings 3.0 紧绷，含 → 3.0-3.5。 |
71	| W2 | **严重** | "你只是没调对参数" | D018 的 teacher-forcing 分布偏移是结构性的，与 loss 设计无关。v1-v7 已覆盖 4 种核心 loss (cumulative v1-v2, maximize v3-v5, smooth_saturation v6, mse_target v7)，MSE+gate_div 是唯一训练收敛方案。四路消融隔离 turn conditioning (TG vs UG) 和 gating 本身 (TG vs LoRA-only)，消除超参解释。 |
72	| W3 | **严重** | GAR 作为唯一代理指标 | 考虑加 1 个简单下游任务 sanity check（如 system prompt instruction following accuracy）。PPL 对比已加入四路 eval（TG PPL > LoRA-only → gates 有害的额外证据）。 |
73	| W4 | **中等** | 无建设性贡献 | Discussion 需要 constructive future directions section: (1) inference-time attention intervention 绕过训练泛化问题; (2) decoupled goal-processing pathway; (3) GAR-aware decoding 而非 GAR-aware training; (4) exposure bias mitigation 技术应用到 auxiliary attention loss。 |
74	| W5 | **中等** | Teacher-forcing insight 不新（exposure bias 文献已知） | 我们的增量: 定量展示 distribution shift 如何具体破坏 auxiliary attention loss（~30× 断层），现有 exposure bias 文献无此分析。Exposure bias 讨论集中在 generation quality degradation，未涉及 auxiliary attention loss 的泛化失败。 |
75	| R1 | 中等 | Novelty of negative result | 核心增量不是 negative result 本身，而是 distribution shift insight（SP1）+ 梯度竞争量化（SP2）+ failure mode taxonomy。 |
76	| R2 | 中等 | 与 Dongre et al. 的关系 | 不说 "we extend Dongre"，而是 "Dongre diagnosed; we attempted the first systematic cure and uncovered fundamental limitations"。核心叙事是 mechanism discovery，非 follow-up work。 |
77	| W6 | **严重** | 引用不足（Dream review: 11篇远不够）| 目标 25-30 篇。必须覆盖: attention sinks (Xiao et al. 2024), Found-in-the-Middle (Ko et al. 2024), gated attention (Qiu et al. 2025), transformer circuits (Elhage et al. 2021), FlexiDepth (Luo et al. 2025), multi-turn eval (MT-Bench-101, MultiChallenge), exposure bias mitigation (Professor Forcing, SEARNN) 等。Paper Agent 写作时负责扩充。|
78	| W7 | **严重** | 单 seed 无方差估计 | 所有实验 seed=42，TG-LoRA 差异 ±0.001 在噪声层。回应: held-out eval 50 conversations 提供 paired bootstrap CI，若 CI 包含 0 则统计支持 "zero benefit"。必要时追加 2 个 seed 的训练。|
79	| W8 | **中等** | 缺 exposure-bias mitigation 实验 | 测试 scheduled sampling / model-generated context 训练能否缩小 ~30× gap。加入 experiment_plan (P1)。如果实验表明 mitigation 确实缩小 gap，论文从 "negative result" 升级为 "negative result + constructive direction"。|
80	| R1 | 中等 | Novelty of negative result | 核心增量不是 negative result 本身，而是 exposure bias 的定量测量（SP1）+ 梯度竞争量化（SP2）+ failure mode taxonomy。 |
81	| R2 | 中等 | 与 Dongre et al. 的关系 | 不说 "we extend Dongre"，而是 "Dongre diagnosed; we attempted the first systematic cure and uncovered fundamental limitations"。核心叙事是 mechanism discovery，非 follow-up work。 |
82	| R3 | 低 | ~30× gap 是否可能是实现 bug | D015 代码逐行对比 + D017 controlled experiments 确认非 bug。Base model 在 ultrachat 和 eval data 上 GAR 均 ~0.01，排除数据分布解释。 |
83	| R4 | ~~低~~ **已核实** | Code-paper 公式语义相反 | **已确认不一致（plan_017 DONE）**。代码正确实现 ReZero-style: `x_{l+1} = x_l + g_l · f_l(x_l)`（gate 缩放子层输出，g→0=层 no-op）。Dream paper.tex 错误写为 `x_{l+1} = g_l · x_l + f_l(x_l)`（gate 缩放残差流，g→0=破坏 skip connection）。**实验数据不受影响**（所有实验用同一份代码）。**Paper Agent 写作时必须**: (1) Method section 用正确公式 `x + g·f(x)`; (2) 机制叙事修正: g→0 = 子层输出被抑制（层变 no-op），NTP 推 g→1 是为保留层计算能力，不是保留 skip connection; (3) NF3 "gate attenuation 2-7%" 指子层贡献缩放，表述正确但需明确。|
84	
85	---
86	
87	## 7. Dongre et al. 关系定位
88	
89	| 维度 | Dongre et al. | 本文 |
90	|------|---------------|------|
91	| 核心问题 | "发生了什么" + "为什么" | "怎么干预" + "为什么干预失败" |
92	| GAR 衰减 | 定义 GAR，12 模型量化衰减 | 独立确认 (Qwen 70.8% raw, 21% normalized) |
93	| 机制分析 | residual probe AUC=0.98 (goal info 持续存在) | NTP-GAR 梯度冲突 + ~30× 泛化 gap + turn conditioning 反转 |
94	| 干预尝试 | goal re-injection (Appendix H, 失败) | ThreadGate residual gating (失败) + UG/LoRA-only 消融 |
95	| 结论 | attention 通道关闭但 residual stream 保留 goal info | 即使在 residual stream 上施加 principled gating，NTP 梯度压制使 gate 无法学到正确的 turn-selective 干预 |
96	
97	**定位语**: Dongre diagnosed the problem; we attempted the first systematic cure and uncovered fundamental limitations. 核心叙事是 mechanism discovery（distribution shift + gradient competition），不是 Dongre 的 follow-up。
98	
99	共同推论: 两种独立干预路线均失败 → lightweight residual gating with auxiliary attention loss 在 teacher-forcing 下面临严重泛化障碍 → 需要 inference-time 干预或 exposure bias mitigation。（注意：scope 限于 lightweight gating，不泛化到所有 attention steering 方法。）
100	
101	---
102	
103	## 8. GAR 定义策略
104	
105	| 用途 | 定义 | Goal tokens | Response tokens | 理由 |
106	|------|------|------------|----------------|------|
107	| 训练信号 | GAR-ours | system prompt + first user query | last token per assistant turn | 更丰富的 goal 信号; last token 作为 summary position 更稳定 |
108	| 主表评估 | GAR-Dongre | system prompt task tokens only | all response tokens | 与 Dongre 可比，审稿人可直接对照 |
109	| 附录评估 | GAR-ours | system prompt + first user query | last token per assistant turn | 两种定义一致性 |
110	
111	**D024 精确化**: GAR-ours 在 same-distribution (ultrachat) text 上 ≈0.49（泛化成功），在 model-generated text 上 ≈0.016（~30× gap）。GAR-Dongre 在两种分布上均低 (~0.01-0.016, 无 gap)。~30× gap 是 text distribution shift 现象，特定于 summary-position attention (GAR-ours)。
112	
113	---
114	
115	## 9. 论文结构草案
116	
117	1. **Abstract** (150-250 words): GAR 衰减问题 → residual probe 证据支撑 gating 动机 → ThreadGate 方法 → 训练成功但推理失败 → 三个失败机制 → 对 attention steering 方法的启示
118	2. **Introduction** (5 段): 多轮对话退化现象 → Dongre 诊断 + residual stream 持续性 → 自然推论: residual gating 应能恢复 → ThreadGate 实验结果: 训练有效推理失败 → 三个失败机制 + 贡献列表
119	3. **Related Work**: multi-turn degradation / residual gating & adaptive depth / attention steering & intervention
120	4. **Background**: GAR 定义 (cite Dongre) + residual stream persistence 证据
121	5. **Method**: ThreadGate 架构（⚠️ 非简单标量 gate：per-layer 2 层 MLP + turn embedding，接收 hidden_state + turn_distance/turn_index，输出 per-token per-layer sigmoid gate 值。公式 g_l = σ(W_2·ReLU(W_1·[proj(x_l); emb(t_d, t_i)] + b_1) + b_2)。Uniform Gate = 同架构但用 constant_vector 替代 turn embedding，仍然 per-layer content-dependent）+ MSE+gate_div loss + v1-v7 loss 设计演化 + 训练设置
122	6. **Experiments**: 四路消融 (TG/UG/LoRA-only/Base) with GAR + PPL dual metrics + 跨模型验证 (Llama-3.1-8B)
123	7. **Analysis**: §6.1 NTP-GAR 梯度冲突观察 → §6.2 Gate turn conditioning (Wilcoxon) → §6.3 **PCGrad 因果排除方向冲突** → §6.4 Distribution shift (exposure bias) 作为主因 → §6.5 attention 可视化 + 训练动力学
124	8. **Discussion**: 为什么 lightweight residual gating 不够 → exposure bias 对 auxiliary attention loss 的具体影响机制 → 潜在解决方向 (inference-time intervention / exposure bias mitigation for auxiliary losses / decoupled pathway / GAR-aware decoding) → **scope 声明: claim 限于 lightweight gating，不泛化到所有 attention steering**
125	9. **Conclusion**: negative result 总结 + 对社区的 actionable 建议
126	
127	### 贡献列表（按 novelty 排序）
128	
129	1. **Exposure bias 对 auxiliary attention loss 泛化性的首个实证刻画**: 实证展示 teacher-forcing distribution shift 如何摧毁 lightweight residual gating 的 auxiliary attention loss 泛化性（~30× training-inference GAR-ours gap），为 teacher-forcing 下的 attention steering 方法提供具体风险标杆
130	2. **NTP-GAR 梯度竞争的逐层量化**: NTP loss 在 gate 参数上的梯度与 GAR loss 冲突，导致 gates 学到反向 turn conditioning（27/28 层 gate 在晚期 turn 趋向 identity）
131	3. **首个 principled residual gating 干预 + 系统性消融**: 基于 Dongre 的 residual stream persistence 证据设计 ThreadGate，v1-v7 覆盖 4 种核心 loss (cumulative v1-v2, maximize v3-v5, smooth_saturation v6, mse_target v7) + 四路消融隔离贡献，为后续研究提供 negative baseline
132	4. **跨模型验证** (Qwen-2.5-7B + Llama-3.1-8B) 确认失败机制的普遍性
133	
134	---
135	
136	## 10. 竞争力评估
137	
138	### Dream Review 结果 (2026-05-19, dream_20260519T135115)
139	- **Best case**: 3.0 (Weak Reject / Findings-level)。主要扣分: claim 过度泛化 (W1), 引用不足 (W6), 单 seed (W7)。
140	- **Median case**: 3.0 (Weak Reject)。同上 + distribution shift insight incremental (W5)。
141	- **Worst case**: 未完成 review（crash），但 imagined experiments 显示最坏情况下 Llama-3 不复现 dramatic pattern。
142	
143	### 修正后预期
144	- **收窄 claim + 扩充引用 + code 验证后**: best 预期 3.5 (Weak Accept / Borderline Conference)。移除两个 Major weakness (W1 overclaim + W6 thin refs)。
145	- **加 bootstrap CI + Llama-3 数据后**: median 预期 3.0-3.5。
146	- **冲 Main 条件**: 上述修正 + exposure-bias mitigation 实验 (W8) + 25-30 references。
147	- **核心差异化**: 不是 "gating 失败了"（弱），而是 "exposure bias 在 auxiliary attention loss 上的首个定量测量 + 失败机制 taxonomy"。
148	- **关键风险**: W5（exposure bias 已知）需要精确定位增量；W7（单 seed）需 bootstrap CI 或追加 seed。
149	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "efee86be-92a4-4064-98ae-ac32540e1e13",
  "isSidechain": false,
  "promptId": "ccea817f-9102-4fb3-b34e-f643df40ae8c",
  "type": "user",
  "uuid": "40e20227-a028-4012-96db-f1f06d61cd1f",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper_framing.md",
      "content": "# Paper Framing: Mechanistic Analysis of Training-Inference Distribution Shift in Attention Steering\n\n> 定位: **Mechanistic insight paper**（不是简单 negative result）。核心卖点是 teacher-forcing→generation 分布偏移如何摧毁 lightweight residual gating 的 auxiliary attention loss 泛化性（~30× 断层的定量证据）。这个 insight 为 auxiliary attention loss 在 teacher-forcing 下的 exposure bias 脆弱性提供首个实证刻画。\n> Novelty 排序: (1) exposure bias 对 auxiliary attention loss 泛化性的首个实证刻画 (~30× gap) > (2) PCGrad 因果排除梯度方向冲突 + \"观察→假设→排除→指向真因\" 完整因果链 (D028) > (3) principled intervention + systematic ablation 的 negative result\n> **⚠️ Dream review D024: \"Cannot\" overclaims, novelty \"first measurement\" 过高, 缺 gradient surgery baseline (PCGrad). 标题改 \"Fails to\", novelty 降级 \"first empirical characterization\"**\n> 目标会议: EMNLP 2026, ARR August cycle, deadline 2026-08-03 (~10.5 weeks)\n> 最后更新: 2026-05-22 (C5 fully confirmed; gap numbers unified to ~30×; M017 修正: PPL -46% 为跨协议伪影, IID PPL 无差异; selective dissociation 撤回; D033 跨变体确认)\n> **⚠️ Llama-3 跨模型验证 = MUST-HAVE**（不含 → Findings 3.0 紧绷；含 → 3.0-3.5）\n\n---\n\n## 1. Title Candidates\n\n- **T1 (推荐)**: Why Lightweight Gating Fails to Fix Multi-Turn Attention Degradation: A Mechanistic Analysis\n- **T2**: The Distribution Shift Trap: Why Training-Time Attention Steering Fails at Inference\n- **T3**: Residual Gating Fails to Recover Goal Attention in Multi-Turn Dialogue\n- **T4**: Lightweight Gating Struggles with Multi-Turn Attention Degradation: Evidence from Exposure Bias\n\n推荐 T1: \"Fails to Fix\" 替代 \"Cannot Fix\"（审稿共识：证据仅支持 tested conditions 下的失败，非绝对否定）。\"Lightweight Gating\" 覆盖标量+uniform gate。\n\n---\n\n## 2. Story Arc\n\nMulti-turn dialogue performance in LLMs degrades as conversations grow longer. Dongre et al. (2026) quantified this through the Goal Accessibility Ratio (GAR), showing 27-48% drops over 50 turns, while their residual stream probes reveal that goal information persists (AUC up to 0.98) even as the attention channel closes. This creates a natural hypothesis: if the information is in the residual stream but attention fails to access it, a learnable gate on the residual connection should recover it. We implement this hypothesis as ThreadGate, a per-layer gating module trained with joint NTP and GAR objectives. ThreadGate successfully optimizes GAR during training (0.02 to 0.48), and this improvement transfers perfectly when evaluated on same-distribution text at inference (GAR-ours = 0.49). However, on model-generated text, GAR-ours collapses to 0.016—a ~30× gap driven by text distribution shift. Our central finding is that attention patterns learned under teacher-forced contexts (gold text) do not generalize to autoregressive generation contexts (model-generated text), the classic exposure bias phenomenon. This distribution shift is structural, independent of loss design or gating architecture. We further identify two coupled mechanisms that amplify the shift: (1) NTP loss dominates gate gradients, causing gates to learn reverse turn conditioning (suppressing at early turns where GAR is high, becoming passive at late turns where intervention is needed); (2) at inference time, gates attenuate residual updates by only 2-7%, far too weak to shift attention patterns. Four-way ablation (ThreadGate vs. Uniform Gate vs. LoRA-only vs. Base) confirms gating provides zero incremental contribution. Notably, this ~30× gap is specific to GAR-ours (last-token attention to goals); GAR-Dongre (all-token attention) shows uniformly low values regardless of text distribution, revealing that exposure bias selectively disrupts summary-position attention patterns. Combined with Dongre et al.'s independent failure of goal re-injection, our results provide the first empirical characterization of how text distribution shift (exposure bias) selectively destroys attention patterns learned through auxiliary losses, and identify the specific mechanisms through which this vulnerability manifests.\n\n---\n\n## 3. Core Claims\n\n| # | Claim | 支撑 | 状态 |\n|---|-------|------|------|\n| C1 | GAR 衰减是真实且严重的结构性现象: Qwen-2.5-7B raw GAR 下降 70.8%, normalized GAR 下降 ~21% | Phase 1 GAR 诊断 | ✅ 已验证 |\n| C2 | Residual gating 训练时在 same-distribution text 上有效优化 GAR-ours (0.48→0.49 泛化成功)，但在 model-generated text 上完全失败 (GAR-ours=0.016, ~30× text distribution shift gap)。GAR-Dongre 在两种分布上均低（~0.01-0.016），无 gap——说明分布偏移选择性影响 summary-position attention pattern。 | v7 训练曲线 + 4-way eval + v7 直接 eval + Reviewer 独立验证 (D024) | ✅ 已验证（precision upgrade） |\n| C3 | 失败机制的因果分析: (1) Distribution shift 是主因（D028 PCGrad 因果排除梯度方向冲突）; (2) NTP 幅度主导 gate 学习 → NF1 反向 turn conditioning; (3) NF3 gate 干预强度不足 2-7%。PCGrad ablation: 消除方向冲突后 cos_sim 围绕 0 震荡(range -0.151 to +0.091)，但 L_GAR 坍塌轨迹不变且无延迟 → 方向冲突非因果因素。**推理端确认（IID same-protocol）**: v9 GAR-ours=0.0151 vs v7=0.0157 (差<0.1pp), **v9 IID PPL=2.780 vs v7=2.784 (差0.004，无改善)**——PCGrad 消除方向冲突后所有可观测指标均 ≈ v7，方向冲突因 NTP 幅度主导而完全 inconsequential | D014 gate-profile + 梯度冲突量化 + **D028 PCGrad 因果排除** + v9 推理 eval + **M017 PPL 修正** | ✅ **End-to-end 完成**: 训练端 + 推理端均确认梯度方向冲突对 GAR 和 PPL 均无因果影响 |\n| C4 | Gating 无增量贡献: 四路消融 LoRA-only ≈ TG ≈ UG（GAR + PPL 双指标）。IID: GAR 差异<0.6pp, PPL 均 ~2.78。**Model-gen (D033): v9 PCGrad=0.0151, UG=0.0149, LoRA-only=0.0245 均接近 baseline 0.0122——~30× gap 在所有训练变体上普遍存在，排除 gating mechanism / turn-conditioning / gradient conflict 作为因果因素** | D021 四路 eval + D033 model-gen eval | ✅ **双重验证**: IID (D021) + model-gen (D033)。model-gen regime 进一步确认 gating 零增量且 GAR collapse 是训练-推理分布偏移的普遍现象 |\n| C5 | 跨模型验证: Llama-3.1-8B 上复现同样的失败模式 | Phase 1 ✅ (GAR decay 80.2%, D042), Phase 2 ✅ (TG gap 27× median, gating zero-increment TG≈LO, LoRA-only N=20 eval) | ✅ Fully confirmed |\n\n---\n\n## 4. Negative Findings (NF)\n\n| # | Finding | 证据 | 叙事角色 |\n|---|---------|------|----------|\n| NF1 | Gate turn conditioning 方向反转: 27/28 层 gate diff (turn1-turn21) < 0，早期 turn 强抑制，晚期 turn passive | D014 eval gate-profile | 解释 why gating fails: NTP 梯度推 gate→1.0，晚期 turn 推力最强 |\n| NF2 | ~30× text distribution shift gap (GAR-ours): ultrachat 文本 0.49 vs 模型生成文本 0.016。Same-distribution 泛化成功（训练 0.48 → ultrachat eval 0.49），cross-distribution 泛化失败。**D033 跨变体确认**: v9 PCGrad (0.0151), UG (0.0149), LoRA-only (0.0245) model-gen GAR 均接近 baseline (0.0122)——gap 独立于训练策略，是 exposure bias 的普遍表现。GAR-Dongre 在两种分布上均低（~0.01-0.019），无 gap——分布偏移选择性影响 summary-position (last token) attention pattern | D015 + 4-way eval + v7 direct eval + D024 + **D033 cross-variant model-gen** | 核心 negative finding。精确定位为 TEXT DISTRIBUTION SHIFT（exposure bias）。D033 确认跨所有训练变体的普遍性。 |\n| NF3 | 推理时 gate attenuation 仅 2-7% (gate_mean=0.93-0.98)，近乎 identity | D014 gate dynamic range 数据 | 解释 why 推理时 GAR 不改善: 干预强度不足 |\n| NF4 | Eval baseline confound (Phase1 base vs Phase2 LoRA 文本不同) | P0 代码分析 | 已修正 → standard_conversations.json 统一 eval |\n\n---\n\n## 5. Key Selling Points\n\n**SP1 (核心卖点): Exposure bias 对 auxiliary attention loss 泛化性的首个实证刻画。** ~30× training-inference GAR-ours gap 提供了 teacher-forcing distribution shift 如何摧毁 auxiliary attention loss 泛化性的实证证据。训练时模型在 gold context 上优化 attention pattern，推理时在自身生成的 context 上条件化——两者分布不同导致 attention pattern 不迁移。虽然 exposure bias 概念本身已知 (Bengio et al. 2015)，且 sequence generation 中有量化先例 (Ranzato et al. 2016, Wiseman & Rush 2016)，但此前无人刻画其对 auxiliary attention loss 的具体影响。我们的 ~30× gap 测量展示了这种脆弱性在 attention steering 场景下的严重程度。**注意：(1) claim scope 严格限于 lightweight residual gating + GAR auxiliary loss 的实测范围，不泛化到所有 attention steering 方法。(2) ~30× gap 在 GAR-ours（last token only, summary-position attention）上测得（IID 0.50 vs model-gen 0.016）；GAR-Dongre（all response tokens）在两种分布上均低（~0.01-0.019），无 gap——表明 exposure bias 选择性影响 summary-position attention pattern，这一差异本身有分析价值。**\n\n**SP2: NTP-GAR 梯度动力学 + PCGrad 因果排除（gradient conflict is inconsequential）。** 观察到 67-79% 的层 NTP-GAR 梯度方向冲突（cos_sim<0）+ NTP 幅度 3-15x 压制 GAR（mag_ratio 7.5→14.7x）。**PCGrad 消融（D028）因果排除方向冲突**：投影后 cos_sim 围绕 0 震荡（range -0.151 to +0.091），L_GAR 坍塌轨迹不变。**推理端确认（IID same-protocol）**: v9 IID PPL = 2.780 vs v7 = 2.784（差 0.004，无改善）; v9 GAR-ours = 0.0151 vs v7 = 0.0157（差 <0.1pp）——**PCGrad 消除方向冲突后所有可观测指标均无变化**（GAR、PPL、NTP 均 ≈ v7）。方向冲突虽然可测量存在于 v7 中，但对训练和推理结果无任何因果影响——10-40× NTP 幅度主导使方向冲突完全无关紧要（inconsequential）。**⚠️ M017: 此前 \"PPL -46%\" 和 \"selective dissociation\" 论述为跨协议对比伪影（model-gen PPL 1.50 vs IID PPL 2.78），已撤回。** **精确 claim scope**: gradient direction conflict is **neither necessary nor sufficient** for the ~30× GAR gap; exposure bias alone is sufficient。NOT necessary: 移除冲突→gap仍在; NOT sufficient: v7有冲突但L_GAR训练时收敛; Exposure bias is sufficient: 训练≠推理分布→GAR泛化失败。**Gate 行为额外 insight**: v9 gate dynamic range 比 v7 更宽 (L15 range 0.33 vs v7 0.21)——PCGrad 给 gate 更大自由度，但 gate 用该自由度更激进地优化 NTP 而非 GAR，说明优化景观固有偏好语言建模目标。\n\n**SP3: Principled 设计动机 + 系统性探索。** Dongre 发现 goal info 在 residual stream 持续存在 (probe AUC=0.98)，residual gating 是最直接的架构响应。v1-v7 覆盖 4 种核心 loss 设计 across 7 training configurations，MSE+gate_div 是唯一训练收敛方案。四路消融严格隔离贡献: TG (learned gate + GAR loss) / UG (uniform gate + GAR loss) / LoRA-only (gate=1.0 fixed + GAR loss, 无 gating 机制) / Base。注意：三个 fine-tuned 变体均使用 GAR loss，消融测试的是 gating 机制的增量贡献，而非 GAR loss 本身的效果。\n\n**SP4: Convergent evidence with Dongre。** Dongre diagnosed the problem; we attempted the first systematic cure and uncovered fundamental limitations。两种独立干预路线（goal re-injection + residual gating）均失败，共同指向 NTP 优化压力下 attention steering 的根本困难。\n\n**SP5: 三阶段训练动力学。** v7 展现 plateau → phase transition → convergence 的清晰训练动力学，证明 MSE 双向 loss 设计本身是 sound 的，问题在泛化而非训练。\n\n---\n\n## 6. Anticipated Reviewer Concerns\n\n| # | 严重度 | 预期质疑 | 回应策略 |\n|---|--------|----------|----------|\n| W1 | **致命** | 单模型验证不够 | Llama-3.1-8B 跨模型验证是 **MUST-HAVE**。Qwen 完整消融 + Llama 复现。不含 Llama → Findings 3.0 紧绷，含 → 3.0-3.5。 |\n| W2 | **严重** | \"你只是没调对参数\" | D018 的 teacher-forcing 分布偏移是结构性的，与 loss 设计无关。v1-v7 已覆盖 4 种核心 loss (cumulative v1-v2, maximize v3-v5, smooth_saturation v6, mse_target v7)，MSE+gate_div 是唯一训练收敛方案。四路消融隔离 turn conditioning (TG vs UG) 和 gating 本身 (TG vs LoRA-only)，消除超参解释。 |\n| W3 | **严重** | GAR 作为唯一代理指标 | 考虑加 1 个简单下游任务 sanity check（如 system prompt instruction following accuracy）。PPL 对比已加入四路 eval（TG PPL > LoRA-only → gates 有害的额外证据）。 |\n| W4 | **中等** | 无建设性贡献 | Discussion 需要 constructive future directions section: (1) inference-time attention intervention 绕过训练泛化问题; (2) decoupled goal-processing pathway; (3) GAR-aware decoding 而非 GAR-aware training; (4) exposure bias mitigation 技术应用到 auxiliary attention loss。 |\n| W5 | **中等** | Teacher-forcing insight 不新（exposure bias 文献已知） | 我们的增量: 定量展示 distribution shift 如何具体破坏 auxiliary attention loss（~30× 断层），现有 exposure bias 文献无此分析。Exposure bias 讨论集中在 generation quality degradation，未涉及 auxiliary attention loss 的泛化失败。 |\n| R1 | 中等 | Novelty of negative result | 核心增量不是 negative result 本身，而是 distribution shift insight（SP1）+ 梯度竞争量化（SP2）+ failure mode taxonomy。 |\n| R2 | 中等 | 与 Dongre et al. 的关系 | 不说 \"we extend Dongre\"，而是 \"Dongre diagnosed; we attempted the first systematic cure and uncovered fundamental limitations\"。核心叙事是 mechanism discovery，非 follow-up work。 |\n| W6 | **严重** | 引用不足（Dream review: 11篇远不够）| 目标 25-30 篇。必须覆盖: attention sinks (Xiao et al. 2024), Found-in-the-Middle (Ko et al. 2024), gated attention (Qiu et al. 2025), transformer circuits (Elhage et al. 2021), FlexiDepth (Luo et al. 2025), multi-turn eval (MT-Bench-101, MultiChallenge), exposure bias mitigation (Professor Forcing, SEARNN) 等。Paper Agent 写作时负责扩充。|\n| W7 | **严重** | 单 seed 无方差估计 | 所有实验 seed=42，TG-LoRA 差异 ±0.001 在噪声层。回应: held-out eval 50 conversations 提供 paired bootstrap CI，若 CI 包含 0 则统计支持 \"zero benefit\"。必要时追加 2 个 seed 的训练。|\n| W8 | **中等** | 缺 exposure-bias mitigation 实验 | 测试 scheduled sampling / model-generated context 训练能否缩小 ~30× gap。加入 experiment_plan (P1)。如果实验表明 mitigation 确实缩小 gap，论文从 \"negative result\" 升级为 \"negative result + constructive direction\"。|\n| R1 | 中等 | Novelty of negative result | 核心增量不是 negative result 本身，而是 exposure bias 的定量测量（SP1）+ 梯度竞争量化（SP2）+ failure mode taxonomy。 |\n| R2 | 中等 | 与 Dongre et al. 的关系 | 不说 \"we extend Dongre\"，而是 \"Dongre diagnosed; we attempted the first systematic cure and uncovered fundamental limitations\"。核心叙事是 mechanism discovery，非 follow-up work。 |\n| R3 | 低 | ~30× gap 是否可能是实现 bug | D015 代码逐行对比 + D017 controlled experiments 确认非 bug。Base model 在 ultrachat 和 eval data 上 GAR 均 ~0.01，排除数据分布解释。 |\n| R4 | ~~低~~ **已核实** | Code-paper 公式语义相反 | **已确认不一致（plan_017 DONE）**。代码正确实现 ReZero-style: `x_{l+1} = x_l + g_l · f_l(x_l)`（gate 缩放子层输出，g→0=层 no-op）。Dream paper.tex 错误写为 `x_{l+1} = g_l · x_l + f_l(x_l)`（gate 缩放残差流，g→0=破坏 skip connection）。**实验数据不受影响**（所有实验用同一份代码）。**Paper Agent 写作时必须**: (1) Method section 用正确公式 `x + g·f(x)`; (2) 机制叙事修正: g→0 = 子层输出被抑制（层变 no-op），NTP 推 g→1 是为保留层计算能力，不是保留 skip connection; (3) NF3 \"gate attenuation 2-7%\" 指子层贡献缩放，表述正确但需明确。|\n\n---\n\n## 7. Dongre et al. 关系定位\n\n| 维度 | Dongre et al. | 本文 |\n|------|---------------|------|\n| 核心问题 | \"发生了什么\" + \"为什么\" | \"怎么干预\" + \"为什么干预失败\" |\n| GAR 衰减 | 定义 GAR，12 模型量化衰减 | 独立确认 (Qwen 70.8% raw, 21% normalized) |\n| 机制分析 | residual probe AUC=0.98 (goal info 持续存在) | NTP-GAR 梯度冲突 + ~30× 泛化 gap + turn conditioning 反转 |\n| 干预尝试 | goal re-injection (Appendix H, 失败) | ThreadGate residual gating (失败) + UG/LoRA-only 消融 |\n| 结论 | attention 通道关闭但 residual stream 保留 goal info | 即使在 residual stream 上施加 principled gating，NTP 梯度压制使 gate 无法学到正确的 turn-selective 干预 |\n\n**定位语**: Dongre diagnosed the problem; we attempted the first systematic cure and uncovered fundamental limitations. 核心叙事是 mechanism discovery（distribution shift + gradient competition），不是 Dongre 的 follow-up。\n\n共同推论: 两种独立干预路线均失败 → lightweight residual gating with auxiliary attention loss 在 teacher-forcing 下面临严重泛化障碍 → 需要 inference-time 干预或 exposure bias mitigation。（注意：scope 限于 lightweight gating，不泛化到所有 attention steering 方法。）\n\n---\n\n## 8. GAR 定义策略\n\n| 用途 | 定义 | Goal tokens | Response tokens | 理由 |\n|------|------|------------|----------------|------|\n| 训练信号 | GAR-ours | system prompt + first user query | last token per assistant turn | 更丰富的 goal 信号; last token 作为 summary position 更稳定 |\n| 主表评估 | GAR-Dongre | system prompt task tokens only | all response tokens | 与 Dongre 可比，审稿人可直接对照 |\n| 附录评估 | GAR-ours | system prompt + first user query | last token per assistant turn | 两种定义一致性 |\n\n**D024 精确化**: GAR-ours 在 same-distribution (ultrachat) text 上 ≈0.49（泛化成功），在 model-generated text 上 ≈0.016（~30× gap）。GAR-Dongre 在两种分布上均低 (~0.01-0.016, 无 gap)。~30× gap 是 text distribution shift 现象，特定于 summary-position attention (GAR-ours)。\n\n---\n\n## 9. 论文结构草案\n\n1. **Abstract** (150-250 words): GAR 衰减问题 → residual probe 证据支撑 gating 动机 → ThreadGate 方法 → 训练成功但推理失败 → 三个失败机制 → 对 attention steering 方法的启示\n2. **Introduction** (5 段): 多轮对话退化现象 → Dongre 诊断 + residual stream 持续性 → 自然推论: residual gating 应能恢复 → ThreadGate 实验结果: 训练有效推理失败 → 三个失败机制 + 贡献列表\n3. **Related Work**: multi-turn degradation / residual gating & adaptive depth / attention steering & intervention\n4. **Background**: GAR 定义 (cite Dongre) + residual stream persistence 证据\n5. **Method**: ThreadGate 架构（⚠️ 非简单标量 gate：per-layer 2 层 MLP + turn embedding，接收 hidden_state + turn_distance/turn_index，输出 per-token per-layer sigmoid gate 值。公式 g_l = σ(W_2·ReLU(W_1·[proj(x_l); emb(t_d, t_i)] + b_1) + b_2)。Uniform Gate = 同架构但用 constant_vector 替代 turn embedding，仍然 per-layer content-dependent）+ MSE+gate_div loss + v1-v7 loss 设计演化 + 训练设置\n6. **Experiments**: 四路消融 (TG/UG/LoRA-only/Base) with GAR + PPL dual metrics + 跨模型验证 (Llama-3.1-8B)\n7. **Analysis**: §6.1 NTP-GAR 梯度冲突观察 → §6.2 Gate turn conditioning (Wilcoxon) → §6.3 **PCGrad 因果排除方向冲突** → §6.4 Distribution shift (exposure bias) 作为主因 → §6.5 attention 可视化 + 训练动力学\n8. **Discussion**: 为什么 lightweight residual gating 不够 → exposure bias 对 auxiliary attention loss 的具体影响机制 → 潜在解决方向 (inference-time intervention / exposure bias mitigation for auxiliary losses / decoupled pathway / GAR-aware decoding) → **scope 声明: claim 限于 lightweight gating，不泛化到所有 attention steering**\n9. **Conclusion**: negative result 总结 + 对社区的 actionable 建议\n\n### 贡献列表（按 novelty 排序）\n\n1. **Exposure bias 对 auxiliary attention loss 泛化性的首个实证刻画**: 实证展示 teacher-forcing distribution shift 如何摧毁 lightweight residual gating 的 auxiliary attention loss 泛化性（~30× training-inference GAR-ours gap），为 teacher-forcing 下的 attention steering 方法提供具体风险标杆\n2. **NTP-GAR 梯度竞争的逐层量化**: NTP loss 在 gate 参数上的梯度与 GAR loss 冲突，导致 gates 学到反向 turn conditioning（27/28 层 gate 在晚期 turn 趋向 identity）\n3. **首个 principled residual gating 干预 + 系统性消融**: 基于 Dongre 的 residual stream persistence 证据设计 ThreadGate，v1-v7 覆盖 4 种核心 loss (cumulative v1-v2, maximize v3-v5, smooth_saturation v6, mse_target v7) + 四路消融隔离贡献，为后续研究提供 negative baseline\n4. **跨模型验证** (Qwen-2.5-7B + Llama-3.1-8B) 确认失败机制的普遍性\n\n---\n\n## 10. 竞争力评估\n\n### Dream Review 结果 (2026-05-19, dream_20260519T135115)\n- **Best case**: 3.0 (Weak Reject / Findings-level)。主要扣分: claim 过度泛化 (W1), 引用不足 (W6), 单 seed (W7)。\n- **Median case**: 3.0 (Weak Reject)。同上 + distribution shift insight incremental (W5)。\n- **Worst case**: 未完成 review（crash），但 imagined experiments 显示最坏情况下 Llama-3 不复现 dramatic pattern。\n\n### 修正后预期\n- **收窄 claim + 扩充引用 + code 验证后**: best 预期 3.5 (Weak Accept / Borderline Conference)。移除两个 Major weakness (W1 overclaim + W6 thin refs)。\n- **加 bootstrap CI + Llama-3 数据后**: median 预期 3.0-3.5。\n- **冲 Main 条件**: 上述修正 + exposure-bias mitigation 实验 (W8) + 25-30 references。\n- **核心差异化**: 不是 \"gating 失败了\"（弱），而是 \"exposure bias 在 auxiliary attention loss 上的首个定量测量 + 失败机制 taxonomy\"。\n- **关键风险**: W5（exposure bias 已知）需要精确定位增量；W7（单 seed）需 bootstrap CI 或追加 seed。\n",
      "numLines": 149,
      "startLine": 1,
      "totalLines": 149
    }
  },
  "sourceToolAssistantUUID": "efee86be-92a4-4064-98ae-ac32540e1e13",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-22T16:07:27.380Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Fo1mhyFQbnNaaBVk1Kkbub`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper_framing.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cfd621f3-6349-40c5-9554-1a79ba6be0d5",
  "isSidechain": false,
  "requestId": "req_011CbHtrr677z2AQaXeHnivM",
  "type": "assistant",
  "uuid": "efee86be-92a4-4064-98ae-ac32540e1e13",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017pRD53BtqaPxdw5hSruSfC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13291,
      "cache_read_input_tokens": 11841,
      "output_tokens": 176,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13291,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 176,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13291,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13291
          },
          "type": "message"
        }
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

_source line 13_

```json
{
  "type": "last-prompt",
  "leafUuid": "40e20227-a028-4012-96db-f1f06d61cd1f",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

### Runtime record

_source line 14_

```json
{
  "type": "ai-title",
  "aiTitle": "Extend Table 2 with failure mechanism column",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

### Assistant

_source line 15 · 2026-05-22T16:08:19.808Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture of the current Table 2 and the failure mechanisms to add. Let me modify the table in appendix.tex.

Current table structure:
- Columns: (unlabeled version), Loss Family, Status, GAR, PPL
- 7 rows: v1 through v7

I need to:
1. Add a "Failure Mechanism" column
2. The table is currently `table` environment with 5 columns `l l l c c`
3. Need to make it wider - probably `table*` with `\scriptsize` or `\small` and/or `tabularx`/`adjustbox`


4. Now I'm mapping each version to its corresponding failure mechanism, checking the user's provided table against what I have to ensure the descriptions align correctly. I'm seeing that the paper organizes the loss variants into four families: cumulative (v1-v2), maximize (v3-v3b-v5), smooth_saturation (v6), and mse_target (v7). The user's failure mechanism table uses different loss family names for v1, but I need to map their failure mechanisms to the paper's existing row structure rather than changing the loss families themselves. So I'm taking the user's failure descriptions and matching them to which paper rows they apply to. make the table unwieldy, so I need to think about how to present this without breaking the layout. I could either keep the failure mechanisms in a separate detailed section below the table, or condense them significantly within the table cells themselves. Generating LaTeX table... Generating the table rows... Adjusting the table formatting for the two-column layout—I'll use `\footnotesize` and a narrower column width for the failure mechanism text to ensure everything fits properly across both columns without crowding.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "40e20227-a028-4012-96db-f1f06d61cd1f",
  "isSidechain": false,
  "requestId": "req_011CbHttCHKasYPzyA8T29Go",
  "type": "assistant",
  "uuid": "6ee6bd5e-d9c1-40f7-a80d-184e00feb58c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CpyzkwHUrGTa6FiCjCkDTE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9728,
      "cache_read_input_tokens": 25132,
      "output_tokens": 3548,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9728,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3548,
          "cache_read_input_tokens": 25132,
          "cache_creation_input_tokens": 9728,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9728
          },
          "type": "message"
        }
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

_source line 16 · 2026-05-22T16:08:19.961Z_

Now I have the table structure and the failure mechanisms. I'll add the "Failure Mechanism" column, switch to `table*` for full-width, and use `\footnotesize` to fit.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6ee6bd5e-d9c1-40f7-a80d-184e00feb58c",
  "isSidechain": false,
  "requestId": "req_011CbHttCHKasYPzyA8T29Go",
  "type": "assistant",
  "uuid": "381dd790-1c1d-4b97-bb33-dfad7afada0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CpyzkwHUrGTa6FiCjCkDTE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9728,
      "cache_read_input_tokens": 25132,
      "output_tokens": 3548,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9728,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3548,
          "cache_read_input_tokens": 25132,
          "cache_creation_input_tokens": 9728,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9728
          },
          "type": "message"
        }
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

_source line 17 · 2026-05-22T16:08:26.552Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01HhFJoTsVfR8R6HEKzTrmbB`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
  "old_string": "\\begin{table}[h]\n\\centering\\small\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
  "new_string": "\\begin{table*}[t]\n\\centering\\footnotesize\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l p{5.8cm} c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{Failure Mechanism} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & Numerical instability from cumulative product; $\\varepsilon$-stabilization insufficient & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & Higher $\\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~\\textbf{converged}  & \\textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "381dd790-1c1d-4b97-bb33-dfad7afada0f",
  "isSidechain": false,
  "requestId": "req_011CbHttCHKasYPzyA8T29Go",
  "type": "assistant",
  "uuid": "12956c40-a1ad-40d4-8864-983128f0fad0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CpyzkwHUrGTa6FiCjCkDTE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9728,
      "cache_read_input_tokens": 25132,
      "output_tokens": 3548,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 9728,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3548,
          "cache_read_input_tokens": 25132,
          "cache_creation_input_tokens": 9728,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 9728
          },
          "type": "message"
        }
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

_source line 18 · 2026-05-22T16:08:26.562Z_

<details><summary>↩ Tool result · reported error · `toolu_01HhFJoTsVfR8R6HEKzTrmbB`</summary>

```text
&lt;tool_use_error>File has been modified since read, either by the user or by a linter. Read it again before attempting to write it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "12956c40-a1ad-40d4-8864-983128f0fad0",
  "isSidechain": false,
  "promptId": "ccea817f-9102-4fb3-b34e-f643df40ae8c",
  "type": "user",
  "uuid": "9c1cf409-cb8c-4563-8e3f-7c021f5f6427",
  "toolUseResult": "Error: File has been modified since read, either by the user or by a linter. Read it again before attempting to write it.",
  "sourceToolAssistantUUID": "12956c40-a1ad-40d4-8864-983128f0fad0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-22T16:08:29.157Z_

<details open><summary>🔧 Tool call — Read · `toolu_01S1GxKxhMLJ9fLbivPET866`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9c1cf409-cb8c-4563-8e3f-7c021f5f6427",
  "isSidechain": false,
  "requestId": "req_011CbHtxYrBhp6W4zq8c4M9n",
  "type": "assistant",
  "uuid": "f39cd442-7597-40d4-92cb-b043f7334f9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WcAScGEiXKr5HbuGYG5hN6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3622,
      "cache_read_input_tokens": 34860,
      "output_tokens": 90,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3622,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 90,
          "cache_read_input_tokens": 34860,
          "cache_creation_input_tokens": 3622,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3622
          },
          "type": "message"
        }
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

_source line 20 · 2026-05-22T16:08:29.165Z_

<details><summary>↩ Tool result · `toolu_01S1GxKxhMLJ9fLbivPET866`</summary>

```text
1	\section{Training Hyperparameters}\label{sec:appendix-hyper}
2	
3	All fine-tuned variants share the following configuration: Qwen-2.5-7B-Instruct base model, LoRA rank 16 ($\alpha$=32) on \texttt{q\_proj} and \texttt{v\_proj}, AdamW optimizer (lr = $2 \times 10^{-4}$, $\beta_1$=0.9, $\beta_2$=0.999), batch size 1 with gradient accumulation 8, 3 epochs over 8K UltraChat conversations, maximum sequence length 2048, seed 42. ThreadGate gates use a 10$\times$ learning rate multiplier and initial bias 1.5 ($\sigma(1.5) \approx 0.82$).
4	
5	\section{Loss Formulation Search}\label{sec:appendix-loss}
6	
7	Table~\ref{tab:loss-iterations} summarizes the seven loss configurations explored before arriving at the final MSE + gate diversity formulation (\S\ref{sec:loss}). Configurations v1--v6 span three alternative loss families; none converged during training.
8	
9	\begin{table}[h]
10	\centering\small
11	\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}
12	\label{tab:loss-iterations}
13	\begin{tabular}{l l l c c}
14	\toprule
15	 & \textbf{Loss Family} & \textbf{Status} & \textbf{GAR} & \textbf{PPL} \\
16	\midrule
17	v1  & Cumulative            & \texttimes~GAR loss $\to$ 0     & ---  & ---  \\
18	v2  & Cumulative + $\varepsilon$ & \texttimes~same trajectory & ---  & ---  \\
19	v3  & Maximize ($\lambda$=2)  & \texttimes~gate frozen        & ---  & ---  \\
20	v3b & Maximize ($\lambda$=10) & \texttimes~identity collapse   & ---  & ---  \\
21	v5  & Maximize ($\lambda$=1)  & \texttimes~identity collapse   & ---  & ---  \\
22	v6  & Smooth saturation       & \texttimes~identity collapse   & ---  & ---  \\
23	v7  & MSE + gate div          & \checkmark~converged           & 0.50 & 2.78 \\
24	\bottomrule
25	\end{tabular}
26	\end{table}
27	
28	\section{Instruction Retention Details}\label{sec:appendix-ir}
29	
30	Across 18 system-prompt constraint types, $\beta$\,=\,3 steering increases content constraint compliance by +23.8\,pp (GAR-compliance $r$\,=\,0.200, $p$\,=\,0.007; McNemar $p$\,=\,0.077), providing exploratory evidence for downstream benefit pending multi-model confirmation.
31	
32	Maximize-family losses ($-\text{mean}(\text{GAR})$) consistently drove gates toward identity: the unbounded objective rewards full pass-through ($g \to 1.0$), collapsing gate diversity (std $<$ 0.025). Bounded variants (smooth saturation) decelerated but did not prevent this collapse, motivating the MSE formulation targeting a finite GAR level.
33	
34	\section{Additional Visualizations}\label{sec:appendix-viz}
35	
36	\subsection{Gate Profile Heatmap}
37	
38	\begin{figure*}[h]
39	\centering
40	\includegraphics[width=0.95\textwidth]{fig_gate_profile_heatmap.pdf}
41	\caption{Per-layer gate values across training for Qwen-2.5-7B (28 layers $\times$ 5 conditions) and Llama-3.1-8B (32 layers $\times$ 1 condition). Early layers (L1, L4--5) consistently receive the lowest gate values across conditions.}
42	\label{fig:gate-heatmap}
43	\end{figure*}
44	
45	\subsection{Cross-Model Gate Profile Comparison}
46	
47	\begin{figure*}[h]
48	\centering
49	\includegraphics[width=0.95\textwidth]{fig_gate_profile_crossmodel.pdf}
50	\caption{Side-by-side gate profiles for Qwen-2.5-7B and Llama-3.1-8B. Qwen dips at early layers (L1\,=\,0.793, L5\,=\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\,=\,0.719). Both models learn layer-selective gating but with architecture-dependent patterns.}
51	\label{fig:gate-crossmodel}
52	\end{figure*}
53	
54	\subsection{Per-Turn AR GAR Decay}
55	
56	\begin{figure*}[h]
57	\centering
58	\includegraphics[width=0.95\textwidth]{fig_ar_gar_perturn.pdf}
59	\caption{GAR decays monotonically across turns under autoregressive generation. Qwen base drops 85\% (turn 1$\to$10), Llama base drops 90\%. The ThreadGate-trained model (AR) shows slight elevation but the same decay pattern, confirming that training-time GAR optimization does not transfer to generation.}
60	\label{fig:ar-gar-perturn}
61	\end{figure*}
62	
63	\subsection{Gate Value Distributions}
64	
65	\begin{figure*}[h]
66	\centering
67	\includegraphics[width=0.95\textwidth]{fig_gate_distribution.pdf}
68	\caption{Per-layer gate value distributions for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\sim$0.94--0.96), confirming zero incremental benefit of the gating mechanism over LoRA-only.}
69	\label{fig:gate-distribution}
70	\end{figure*}
71	
72	\subsection{Training Loss Curves}
73	
74	\begin{figure*}[h]
75	\centering
76	\includegraphics[width=0.95\textwidth]{fig_training_loss_curves.pdf}
77	\caption{NTP, GAR, and total loss trajectories. GAR loss collapses to near-zero within the first epoch across all variants, while NTP loss converges normally.}
78	\label{fig:training-loss}
79	\end{figure*}
80	
81	\input{../artifacts/table_steering_full}
82	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f39cd442-7597-40d4-92cb-b043f7334f9f",
  "isSidechain": false,
  "promptId": "ccea817f-9102-4fb3-b34e-f643df40ae8c",
  "type": "user",
  "uuid": "82262de2-4242-468f-9cc1-292be13e95c3",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
      "content": "\\section{Training Hyperparameters}\\label{sec:appendix-hyper}\n\nAll fine-tuned variants share the following configuration: Qwen-2.5-7B-Instruct base model, LoRA rank 16 ($\\alpha$=32) on \\texttt{q\\_proj} and \\texttt{v\\_proj}, AdamW optimizer (lr = $2 \\times 10^{-4}$, $\\beta_1$=0.9, $\\beta_2$=0.999), batch size 1 with gradient accumulation 8, 3 epochs over 8K UltraChat conversations, maximum sequence length 2048, seed 42. ThreadGate gates use a 10$\\times$ learning rate multiplier and initial bias 1.5 ($\\sigma(1.5) \\approx 0.82$).\n\n\\section{Loss Formulation Search}\\label{sec:appendix-loss}\n\nTable~\\ref{tab:loss-iterations} summarizes the seven loss configurations explored before arriving at the final MSE + gate diversity formulation (\\S\\ref{sec:loss}). Configurations v1--v6 span three alternative loss families; none converged during training.\n\n\\begin{table}[h]\n\\centering\\small\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Instruction Retention Details}\\label{sec:appendix-ir}\n\nAcross 18 system-prompt constraint types, $\\beta$\\,=\\,3 steering increases content constraint compliance by +23.8\\,pp (GAR-compliance $r$\\,=\\,0.200, $p$\\,=\\,0.007; McNemar $p$\\,=\\,0.077), providing exploratory evidence for downstream benefit pending multi-model confirmation.\n\nMaximize-family losses ($-\\text{mean}(\\text{GAR})$) consistently drove gates toward identity: the unbounded objective rewards full pass-through ($g \\to 1.0$), collapsing gate diversity (std $<$ 0.025). Bounded variants (smooth saturation) decelerated but did not prevent this collapse, motivating the MSE formulation targeting a finite GAR level.\n\n\\section{Additional Visualizations}\\label{sec:appendix-viz}\n\n\\subsection{Gate Profile Heatmap}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gate_profile_heatmap.pdf}\n\\caption{Per-layer gate values across training for Qwen-2.5-7B (28 layers $\\times$ 5 conditions) and Llama-3.1-8B (32 layers $\\times$ 1 condition). Early layers (L1, L4--5) consistently receive the lowest gate values across conditions.}\n\\label{fig:gate-heatmap}\n\\end{figure*}\n\n\\subsection{Cross-Model Gate Profile Comparison}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gate_profile_crossmodel.pdf}\n\\caption{Side-by-side gate profiles for Qwen-2.5-7B and Llama-3.1-8B. Qwen dips at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719). Both models learn layer-selective gating but with architecture-dependent patterns.}\n\\label{fig:gate-crossmodel}\n\\end{figure*}\n\n\\subsection{Per-Turn AR GAR Decay}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_ar_gar_perturn.pdf}\n\\caption{GAR decays monotonically across turns under autoregressive generation. Qwen base drops 85\\% (turn 1$\\to$10), Llama base drops 90\\%. The ThreadGate-trained model (AR) shows slight elevation but the same decay pattern, confirming that training-time GAR optimization does not transfer to generation.}\n\\label{fig:ar-gar-perturn}\n\\end{figure*}\n\n\\subsection{Gate Value Distributions}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gate_distribution.pdf}\n\\caption{Per-layer gate value distributions for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\\sim$0.94--0.96), confirming zero incremental benefit of the gating mechanism over LoRA-only.}\n\\label{fig:gate-distribution}\n\\end{figure*}\n\n\\subsection{Training Loss Curves}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_training_loss_curves.pdf}\n\\caption{NTP, GAR, and total loss trajectories. GAR loss collapses to near-zero within the first epoch across all variants, while NTP loss converges normally.}\n\\label{fig:training-loss}\n\\end{figure*}\n\n\\input{../artifacts/table_steering_full}\n",
      "numLines": 82,
      "startLine": 1,
      "totalLines": 82
    }
  },
  "sourceToolAssistantUUID": "f39cd442-7597-40d4-92cb-b043f7334f9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 21_

```json
{
  "type": "last-prompt",
  "leafUuid": "82262de2-4242-468f-9cc1-292be13e95c3",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

### Runtime record

_source line 22_

```json
{
  "type": "ai-title",
  "aiTitle": "Extend Table 2 with failure mechanism column",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

### Tool call

_source line 23 · 2026-05-22T16:08:39.060Z_

<details open><summary>🔧 Tool call — Edit · `toolu_013xhN4ZzTFADaudy7qTgQiV`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
  "old_string": "\\begin{table}[h]\n\\centering\\small\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
  "new_string": "\\begin{table*}[t]\n\\centering\\footnotesize\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l p{5.8cm} c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{Failure Mechanism} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & Numerical instability from cumulative product; $\\varepsilon$-stabilization insufficient & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & Higher $\\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~\\textbf{converged}  & \\textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "82262de2-4242-468f-9cc1-292be13e95c3",
  "isSidechain": false,
  "requestId": "req_011CbHtxkTgi37DnGDx8wUGq",
  "type": "assistant",
  "uuid": "13d33ef2-399c-4eef-b885-be3c6b8ed2ba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QwfXPGg5cfzDLkaSbdN3i5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1910,
      "cache_read_input_tokens": 38482,
      "output_tokens": 1049,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1910,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1049,
          "cache_read_input_tokens": 38482,
          "cache_creation_input_tokens": 1910,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1910
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-22T16:08:39.107Z_

<details><summary>↩ Tool result · `toolu_013xhN4ZzTFADaudy7qTgQiV`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "13d33ef2-399c-4eef-b885-be3c6b8ed2ba",
  "isSidechain": false,
  "promptId": "ccea817f-9102-4fb3-b34e-f643df40ae8c",
  "type": "user",
  "uuid": "9727efc3-2829-42a8-92cf-2cbfab90cd0b",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
    "oldString": "\\begin{table}[h]\n\\centering\\small\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
    "newString": "\\begin{table*}[t]\n\\centering\\footnotesize\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l p{5.8cm} c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{Failure Mechanism} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & Numerical instability from cumulative product; $\\varepsilon$-stabilization insufficient & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & Higher $\\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~\\textbf{converged}  & \\textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}",
    "originalFile": "\\section{Training Hyperparameters}\\label{sec:appendix-hyper}\n\nAll fine-tuned variants share the following configuration: Qwen-2.5-7B-Instruct base model, LoRA rank 16 ($\\alpha$=32) on \\texttt{q\\_proj} and \\texttt{v\\_proj}, AdamW optimizer (lr = $2 \\times 10^{-4}$, $\\beta_1$=0.9, $\\beta_2$=0.999), batch size 1 with gradient accumulation 8, 3 epochs over 8K UltraChat conversations, maximum sequence length 2048, seed 42. ThreadGate gates use a 10$\\times$ learning rate multiplier and initial bias 1.5 ($\\sigma(1.5) \\approx 0.82$).\n\n\\section{Loss Formulation Search}\\label{sec:appendix-loss}\n\nTable~\\ref{tab:loss-iterations} summarizes the seven loss configurations explored before arriving at the final MSE + gate diversity formulation (\\S\\ref{sec:loss}). Configurations v1--v6 span three alternative loss families; none converged during training.\n\n\\begin{table}[h]\n\\centering\\small\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Instruction Retention Details}\\label{sec:appendix-ir}\n\nAcross 18 system-prompt constraint types, $\\beta$\\,=\\,3 steering increases content constraint compliance by +23.8\\,pp (GAR-compliance $r$\\,=\\,0.200, $p$\\,=\\,0.007; McNemar $p$\\,=\\,0.077), providing exploratory evidence for downstream benefit pending multi-model confirmation.\n\nMaximize-family losses ($-\\text{mean}(\\text{GAR})$) consistently drove gates toward identity: the unbounded objective rewards full pass-through ($g \\to 1.0$), collapsing gate diversity (std $<$ 0.025). Bounded variants (smooth saturation) decelerated but did not prevent this collapse, motivating the MSE formulation targeting a finite GAR level.\n\n\\section{Additional Visualizations}\\label{sec:appendix-viz}\n\n\\subsection{Gate Profile Heatmap}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gate_profile_heatmap.pdf}\n\\caption{Per-layer gate values across training for Qwen-2.5-7B (28 layers $\\times$ 5 conditions) and Llama-3.1-8B (32 layers $\\times$ 1 condition). Early layers (L1, L4--5) consistently receive the lowest gate values across conditions.}\n\\label{fig:gate-heatmap}\n\\end{figure*}\n\n\\subsection{Cross-Model Gate Profile Comparison}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gate_profile_crossmodel.pdf}\n\\caption{Side-by-side gate profiles for Qwen-2.5-7B and Llama-3.1-8B. Qwen dips at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719). Both models learn layer-selective gating but with architecture-dependent patterns.}\n\\label{fig:gate-crossmodel}\n\\end{figure*}\n\n\\subsection{Per-Turn AR GAR Decay}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_ar_gar_perturn.pdf}\n\\caption{GAR decays monotonically across turns under autoregressive generation. Qwen base drops 85\\% (turn 1$\\to$10), Llama base drops 90\\%. The ThreadGate-trained model (AR) shows slight elevation but the same decay pattern, confirming that training-time GAR optimization does not transfer to generation.}\n\\label{fig:ar-gar-perturn}\n\\end{figure*}\n\n\\subsection{Gate Value Distributions}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gate_distribution.pdf}\n\\caption{Per-layer gate value distributions for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\\sim$0.94--0.96), confirming zero incremental benefit of the gating mechanism over LoRA-only.}\n\\label{fig:gate-distribution}\n\\end{figure*}\n\n\\subsection{Training Loss Curves}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_training_loss_curves.pdf}\n\\caption{NTP, GAR, and total loss trajectories. GAR loss collapses to near-zero within the first epoch across all variants, while NTP loss converges normally.}\n\\label{fig:training-loss}\n\\end{figure*}\n\n\\input{../artifacts/table_steering_full}\n",
    "structuredPatch": [
      {
        "oldStart": 6,
        "oldLines": 24,
        "newStart": 6,
        "newLines": 24,
        "lines": [
          " ",
          " Table~\\ref{tab:loss-iterations} summarizes the seven loss configurations explored before arriving at the final MSE + gate diversity formulation (\\S\\ref{sec:loss}). Configurations v1--v6 span three alternative loss families; none converged during training.",
          " ",
          "-\\begin{table}[h]",
          "-\\centering\\small",
          "-\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration.}",
          "+\\begin{table*}[t]",
          "+\\centering\\footnotesize",
          "+\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}",
          " \\label{tab:loss-iterations}",
          "-\\begin{tabular}{l l l c c}",
          "+\\begin{tabular}{l l l p{5.8cm} c c}",
          " \\toprule",
          "- & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{GAR} & \\textbf{PPL} \\\\",
          "+ & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{Failure Mechanism} & \\textbf{GAR} & \\textbf{PPL} \\\\",
          " \\midrule",
          "-v1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & ---  & ---  \\\\",
          "-v2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & ---  & ---  \\\\",
          "-v3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & ---  & ---  \\\\",
          "-v3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & ---  & ---  \\\\",
          "-v5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & ---  & ---  \\\\",
          "-v6  & Smooth saturation       & \\texttimes~identity collapse   & ---  & ---  \\\\",
          "-v7  & MSE + gate div          & \\checkmark~converged           & 0.50 & 2.78 \\\\",
          "+v1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\\\",
          "+v2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & Numerical instability from cumulative product; $\\varepsilon$-stabilization insufficient & ---  & ---  \\\\",
          "+v3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\\\",
          "+v3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & Higher $\\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\\\",
          "+v5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\\\",
          "+v6  & Smooth saturation       & \\texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\\\",
          "+v7  & MSE + gate div          & \\checkmark~\\textbf{converged}  & \\textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\\\",
          " \\bottomrule",
          " \\end{tabular}",
          "-\\end{table}",
          "+\\end{table*}",
          " ",
          " \\section{Instruction Retention Details}\\label{sec:appendix-ir}",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "13d33ef2-399c-4eef-b885-be3c6b8ed2ba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 25 · 2026-05-22T16:08:44.052Z_

Table 2 已更新：

- 新增 **Failure Mechanism** 列（`p{5.8cm}` 宽度）
- v1–v6 各填入一句话失败原因
- v7 行 status 和 failure mechanism 均加粗标记成功
- `table` → `table*`（双栏全宽），`\small` → `\footnotesize` 适配新列宽度

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9727efc3-2829-42a8-92cf-2cbfab90cd0b",
  "isSidechain": false,
  "requestId": "req_011CbHtyUT3xTHbrVxrAMQQZ",
  "type": "assistant",
  "uuid": "ceb64ce7-7a46-4f95-a8d9-d040351e83de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NUCLjaRVxQj2Lw5pVxpAm6",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1105,
      "cache_read_input_tokens": 40392,
      "output_tokens": 117,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1105,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 117,
          "cache_read_input_tokens": 40392,
          "cache_creation_input_tokens": 1105,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1105
          },
          "type": "message"
        }
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
  "leafUuid": "ceb64ce7-7a46-4f95-a8d9-d040351e83de",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

### Runtime record

_source line 27_

```json
{
  "type": "ai-title",
  "aiTitle": "Extend Table 2 with failure mechanism column",
  "sessionId": "42862026-8466-421c-acf7-d5e4934cde8c"
}
```

---

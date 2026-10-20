# Research conversation: <project_context> # 项目: symb_invariant_consensus ## 运行环境 - 服务器名: westd-16639 - SSH 连接命令: ssh westd-16639 # 必须用此命令，~/.ssh — Part 1 of 2

**Beyond Self-Consistency: Self-Extracted Constraints Reduce to Majority Voting under Zero-Shot Extraction (July export snapshot)** · Conversation logs

[Transcript overview](../research-conversation-project-context-symb-invariant-consensus-westd-16639-ssh-ssh-westd-16639-ssh-copy-176.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/c4/c4b42035807b9d51b4e0.json)

## Before a recorded user message

## Before a recorded user message

2 recorded events


### Runtime record

_source line 1 · 2026-05-24T04:28:16.546Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-24T04:28:16.546Z",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "content": "&lt;project_context>\n# 项目: symb_invariant_consensus\n\n## 运行环境\n- 服务器名: westd-16639\n- SSH 连接命令: ssh westd-16639  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/symb_invariant_consensus\n\n## ⚠️ 活跃约束（必须遵守）\n\n- **C001**: 所有实验代码写完后必须先 dry-run 验证（python 可用性、路径存在性、端口无冲突、数据文件存在）再正式部署运行（原因：多次出现代码部署后才发现 python command not found、模型路径不存在、GPU/端口冲突等低级错误，浪费 GPU 时间和调试周期。用户明确要求。）\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n**紧急任务：投稿前全文数字追溯审计（DDL 明天）**\n\n## 论文文件位置\n本地路径：`/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/`\n\n.tex 文件清单（全部需要扫描）：\n- abstract.tex\n- introduction.tex\n- method.tex\n- experiments.tex\n- analysis.tex（包含 Table 2 等核心数据表）\n- diagnosis.tex\n- solutions.tex\n- cross_arch.tex（如存在）\n- discussion.tex\n- limitations_content.tex\n- conclusion.tex\n- appendix.tex（包含 tab:multi-seed 多种子表格等）\n- related_work.tex\n\nFigure 生成脚本：\n- `docs/paper/figures/gen_f6_kappa_accuracy_scatter.py`\n- `docs/paper/figures/gen_capability_gap_scatter.py`\n\n## 任务 1：全文数字提取 + registry 追溯\n\n逐个读取每个 .tex 文件，提取所有数值：\n- accuracy 百分比（如 85.83%）\n- Δ 差值（如 -0.17pp）\n- p-value（如 p<0.001）\n- 样本量 n（如 n=600, n=204）\n- Bias Ratio BR（如 BR=2.31）\n- Cohen's κ\n- 实验条件数量\n- 其他定量 claim\n\n对每个数值，尝试追溯到 registry.yaml 中的 experiment ID。用 `read_registry` 查看实验的 metrics 字段。\n\n重点关注：\n- Table 1（主结果表）的所有 cell\n- Table 2（frontier/SCB 表）的所有 cell\n- Table 3（cross-arch/combo 表）的所有 cell\n- Abstract 中的汇总数字\n- Introduction 中引用的数字\n\n## 任务 2：跨位置一致性检查\n\n检查以下一致性：\n1. Abstract 数字 = 正文数字 = Table cell（同一个 claim 在不同位置出现的值必须相同）\n2. 正文中 \"Table X shows Y%\" 的 Y 与 Table 实际 cell 值一致\n3. 四舍五入位数全篇统一（通常 accuracy 保留 2 位小数，Δ 保留 2 位小数）\n4. Table caption 里的 n 值与表内行数/数据点数一致\n5. \"X tested conditions\" 数量与实际实验条件数一致\n\n## 任务 3：Figure 数据源验证\n\n读取两个 Figure 生成脚本：\n- `gen_f6_kappa_accuracy_scatter.py`\n- `gen_capability_gap_scatter.py`\n\n检查：\n- 脚本中硬编码的数据点是否与 Table/正文一致\n- 数据源文件路径是否存在\n- 生成的 PDF 日期是否在最近的数据修正之后（关注 capability_gap_scatter.pdf 5/23, f6_kappa 5/22）\n\n## 任务 4：问题修复\n\n发现不一致时：\n1. 记录问题（文件、行号、期望值 vs 实际值）\n2. 确定哪个值是正确的（以 registry 为 truth source）\n3. 用 Edit 工具修复 .tex 文件\n4. 修复后记录修复清单\n\n## 输出格式\n\n```\n### 审计结果摘要\n\n**扫描文件数**: X\n**提取数值数**: X\n**可追溯到 registry 的数值**: X/Y\n\n### 发现的不一致\n1. [文件:行号] 描述问题 | 期望值 → 实际值 | 状态: 已修复/待确认\n2. ...\n\n### Figure 验证\n- Figure X: 数据源一致 ✓ / 不一致 ✗（详情）\n- ...\n\n### 未修复项（需要 Director 决策）\n1. ...\n```\n\n注意：\n- appendix.tex 中的 tab:multi-seed 表格目前只有 Mistral PW 和 LLaMA PW 数据，Qwen3 数据还在采集中，暂不审计 Qwen3 部分\n- 已知 seed42 Qwen3 canonical: SC=85.83%, SICA=85.67%（Table 1 值）\n- 已知 o3 数据：SC=82.65%, n_err=34, BR=1.66（已在 analysis.tex 中验证一致）"
}
````

---


### Runtime record

_source line 2 · 2026-05-24T04:28:16.549Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-24T04:28:16.549Z",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


## Round 1

## Round 1

126 recorded events


### User

_source line 3 · 2026-05-24T04:28:16.582Z_

&lt;project_context>
# 项目: symb_invariant_consensus

## 运行环境
- 服务器名: westd-16639
- SSH 连接命令: ssh westd-16639  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/symb_invariant_consensus

## ⚠️ 活跃约束（必须遵守）

- **C001**: 所有实验代码写完后必须先 dry-run 验证（python 可用性、路径存在性、端口无冲突、数据文件存在）再正式部署运行（原因：多次出现代码部署后才发现 python command not found、模型路径不存在、GPU/端口冲突等低级错误，浪费 GPU 时间和调试周期。用户明确要求。）


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
**紧急任务：投稿前全文数字追溯审计（DDL 明天）**

## 论文文件位置
本地路径：`/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/`

.tex 文件清单（全部需要扫描）：
- abstract.tex
- introduction.tex
- method.tex
- experiments.tex
- analysis.tex（包含 Table 2 等核心数据表）
- diagnosis.tex
- solutions.tex
- cross_arch.tex（如存在）
- discussion.tex
- limitations_content.tex
- conclusion.tex
- appendix.tex（包含 tab:multi-seed 多种子表格等）
- related_work.tex

Figure 生成脚本：
- `docs/paper/figures/gen_f6_kappa_accuracy_scatter.py`
- `docs/paper/figures/gen_capability_gap_scatter.py`

## 任务 1：全文数字提取 + registry 追溯

逐个读取每个 .tex 文件，提取所有数值：
- accuracy 百分比（如 85.83%）
- Δ 差值（如 -0.17pp）
- p-value（如 p<0.001）
- 样本量 n（如 n=600, n=204）
- Bias Ratio BR（如 BR=2.31）
- Cohen's κ
- 实验条件数量
- 其他定量 claim

对每个数值，尝试追溯到 registry.yaml 中的 experiment ID。用 `read_registry` 查看实验的 metrics 字段。

重点关注：
- Table 1（主结果表）的所有 cell
- Table 2（frontier/SCB 表）的所有 cell
- Table 3（cross-arch/combo 表）的所有 cell
- Abstract 中的汇总数字
- Introduction 中引用的数字

## 任务 2：跨位置一致性检查

检查以下一致性：
1. Abstract 数字 = 正文数字 = Table cell（同一个 claim 在不同位置出现的值必须相同）
2. 正文中 "Table X shows Y%" 的 Y 与 Table 实际 cell 值一致
3. 四舍五入位数全篇统一（通常 accuracy 保留 2 位小数，Δ 保留 2 位小数）
4. Table caption 里的 n 值与表内行数/数据点数一致
5. "X tested conditions" 数量与实际实验条件数一致

## 任务 3：Figure 数据源验证

读取两个 Figure 生成脚本：
- `gen_f6_kappa_accuracy_scatter.py`
- `gen_capability_gap_scatter.py`

检查：
- 脚本中硬编码的数据点是否与 Table/正文一致
- 数据源文件路径是否存在
- 生成的 PDF 日期是否在最近的数据修正之后（关注 capability_gap_scatter.pdf 5/23, f6_kappa 5/22）

## 任务 4：问题修复

发现不一致时：
1. 记录问题（文件、行号、期望值 vs 实际值）
2. 确定哪个值是正确的（以 registry 为 truth source）
3. 用 Edit 工具修复 .tex 文件
4. 修复后记录修复清单

## 输出格式

```
### 审计结果摘要

**扫描文件数**: X
**提取数值数**: X
**可追溯到 registry 的数值**: X/Y

### 发现的不一致
1. [文件:行号] 描述问题 | 期望值 → 实际值 | 状态: 已修复/待确认
2. ...

### Figure 验证
- Figure X: 数据源一致 ✓ / 不一致 ✗（详情）
- ...

### 未修复项（需要 Director 决策）
1. ...
```

注意：
- appendix.tex 中的 tab:multi-seed 表格目前只有 Mistral PW 和 LLaMA PW 数据，Qwen3 数据还在采集中，暂不审计 Qwen3 部分
- 已知 seed42 Qwen3 canonical: SC=85.83%, SICA=85.67%（Table 1 值）
- 已知 o3 数据：SC=82.65%, n_err=34, BR=1.66（已在 analysis.tex 中验证一致）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "6265e7d8-a3cc-4ab7-a0e4-ffc15bacd76f",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Runtime record

_source line 4 · 2026-05-24T04:28:16.581Z_

```json
{
  "parentUuid": "6265e7d8-a3cc-4ab7-a0e4-ffc15bacd76f",
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
  "uuid": "9c0d2d5c-18f5-4021-a85a-8dc89c10a19c",
  "timestamp": "2026-05-24T04:28:16.581Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---


### Runtime record

_source line 5 · 2026-05-24T04:28:16.581Z_

```json
{
  "parentUuid": "9c0d2d5c-18f5-4021-a85a-8dc89c10a19c",
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
  "uuid": "c2df0cbf-74f5-4aa4-aca9-4d415e50fc2c",
  "timestamp": "2026-05-24T04:28:16.581Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---


### Runtime record

_source line 6 · 2026-05-24T04:28:16.581Z_

```json
{
  "parentUuid": "c2df0cbf-74f5-4aa4-aca9-4d415e50fc2c",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "d74e960e-185e-45a9-9f02-55ee2b012ab3",
  "timestamp": "2026-05-24T04:28:16.581Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
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
  "aiTitle": "Audit paper numerics before submission deadline",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Assistant

_source line 8 · 2026-05-24T04:28:23.139Z_

<details><summary>Logged reasoning block</summary>

```text
This is a comprehensive audit task for a research paper before submission. Let me break it down:

1. Read all .tex files and extract numerical values
2. Cross-reference with registry.yaml
3. Check cross-location consistency
4. Verify figure data sources
5. Fix any inconsistencies

Let me start by reading the registry and all .tex files. I'll parallelize the reads as much as possible.

Let me first load the MCP tools I'll need, then start reading files in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d74e960e-185e-45a9-9f02-55ee2b012ab3",
  "isSidechain": false,
  "requestId": "req_011CbLmBeL2rWPyc2MyvbSVq",
  "type": "assistant",
  "uuid": "c1c7040f-9c22-44d2-920a-6115477cb715",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UfK77Av3fu4URSdCdia3MQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13021,
      "cache_read_input_tokens": 11841,
      "output_tokens": 249,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13021,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 249,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13021,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13021
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-24T04:28:24.157Z_

开始全文数字审计。先加载工具和读取所有文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c1c7040f-9c22-44d2-920a-6115477cb715",
  "isSidechain": false,
  "requestId": "req_011CbLmBeL2rWPyc2MyvbSVq",
  "type": "assistant",
  "uuid": "c932bcff-cd13-429b-bc05-75ef860cddf1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UfK77Av3fu4URSdCdia3MQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13021,
      "cache_read_input_tokens": 11841,
      "output_tokens": 249,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13021,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 249,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13021,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13021
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-24T04:28:25.442Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01YGBV32e1tEfXN3wW1C1zrG`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c932bcff-cd13-429b-bc05-75ef860cddf1",
  "isSidechain": false,
  "requestId": "req_011CbLmBeL2rWPyc2MyvbSVq",
  "type": "assistant",
  "uuid": "80861c2f-f461-49f8-9bb2-5f9f6883e8cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UfK77Av3fu4URSdCdia3MQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13021,
      "cache_read_input_tokens": 11841,
      "output_tokens": 249,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13021,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 249,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13021,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13021
          },
          "type": "message"
        }
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

_source line 11 · 2026-05-24T04:28:25.452Z_

<details><summary>↩ Tool result · `toolu_01YGBV32e1tEfXN3wW1C1zrG`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "80861c2f-f461-49f8-9bb2-5f9f6883e8cf",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "341c2685-75f1-48aa-9cc8-3a022d0aa636",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 25
  },
  "sourceToolAssistantUUID": "80861c2f-f461-49f8-9bb2-5f9f6883e8cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Assistant

_source line 12 · 2026-05-24T04:28:27.678Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the registry and all .tex files in parallel. I'll start with the registry and the .tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "341c2685-75f1-48aa-9cc8-3a022d0aa636",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "354efaeb-249e-47c5-adf0-369e5fb57911",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 13 · 2026-05-24T04:28:28.683Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_0134w9o545HbRqxEqQ88GmHH`</summary>

```json
{
  "project": "symb_invariant_consensus",
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
  "parentUuid": "354efaeb-249e-47c5-adf0-369e5fb57911",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "26584dc6-d3d1-44ec-94f9-311d58cc9d1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 14 · 2026-05-24T04:28:29.626Z_

<details><summary>↩ Tool result · `toolu_0134w9o545HbRqxEqQ88GmHH`</summary>

```text
Error: result (280,135 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "26584dc6-d3d1-44ec-94f9-311d58cc9d1a",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "03a69143-1125-4f46-a9f9-306a0f7931ca",
  "toolUseResult": "Error: result (280,135 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp-multi-seed-qwen25-pw-seed789-v2\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-23T04:10:25.973Z\", \"updated_at\": \"2026-05-24T04:01:31.277Z\", \"hypothesis\": \"Qwen2.5-14B PW seed789 多种子复制（第三次尝试，独立 vLLM on cuda:2 port 8007）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。前两次因 vLLM 配置问题失败。\", \"parent\": \"exp-multi-seed-qwen25\", \"spec\": {\"command\": \"python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8007 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen25_pw_seed789/results.json\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:2\"], \"pid\": \"740841\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-qwen25-pw-seed789-v2.log\", \"submitted_at\": \"2026-05-23T04:10:47.302Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-24T04:01:30.322Z\"}}, \"exp-multi-seed-llama-pw-seed789-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T05:56:24.810Z\", \"updated_at\": \"2026-05-23T20:37:24.235Z\", \"hypothesis\": \"LLaMA-3.1-8B PW seed789 多种子复制（westd-30973 cuda:1 全新运行）。替代 16639 cuda:0 上的慢速运行（12/600）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。\", \"parent\": \"exp-multi-seed-llama-pw\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8001 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/llama8b_pw_seed789_v2/results.json\\\"\", \"server\": \"westd-30973\", \"gpu\": [\"cuda:1\"], \"pid\": \"6018\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-llama-pw-seed789-v2.log\", \"submitted_at\": \"2026-05-23T06:09:20.553Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\", \"checkpoint_path\": \"westd-16639:/root/symb_invariant_consensus/results/multi_seed/llama8b_pw_seed789/\", \"wall_clock_seconds\": 52083.7, \"gpu_hours\": 14.47}, \"notes\": \"冗余实验。seed789 完整结果在 westd-16639 (600/600, SC=71.17%, SICA=66.50% alphabetical corrected)。30973 上的 v2/v3 恢复进程已全部 kill。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-23T20:37:24.235Z\"}, \"exp-multi-seed-qwen25-pw-seed789-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T05:56:23.947Z\", \"updated_at\": \"2026-05-23T20:34:39.605Z\", \"hypothesis\": \"Qwen2.5-14B PW seed789 多种子复制（westd-30973 cuda:0 全新运行）。替代 v2 在 16639 cuda:2 上的慢速运行（53/600）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。\", \"parent\": \"exp-multi-seed-qwen25\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8000 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen25_pw_seed789_v3/results.json\\\"\", \"server\": \"westd-30973\", \"gpu\": [\"cuda:0\"], \"pid\": \"6049\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-qwen25-pw-seed789-v3.log\", \"submitted_at\": \"2026-05-23T06:09:22.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\", \"wall_clock_seconds\": 50826.1, \"gpu_hours\": 14.12}, \"notes\": \"westd-30973 上 339/600 处被 SIGTERM kill (May 23 12:40 UTC)。无需恢复——原始版本 exp-multi-seed-qwen25-pw-seed789-v2 在 westd-16639 上已有 600/600 完整结果。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-23T20:16:28.324Z\"}, \"exp-multi-seed-llama-pw-seed456-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T05:56:25.703Z\", \"updated_at\": \"2026-05-23T20:34:32.186Z\", \"hypothesis\": \"LLaMA-3.1-8B PW seed456 多种子复制（westd-30973 cuda:2 全新运行）。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42/123/789 组成 4-seed 覆盖。\", \"parent\": \"exp-multi-seed-llama-pw\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8002 --seed 456 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/llama8b_pw_seed456_v2/results.json\\\"\", \"server\": \"westd-30973\", \"gpu\": [\"cuda:2\"], \"pid\": \"6088\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-llama-pw-seed456-v2.log\", \"submitted_at\": \"2026-05-23T06:09:35.633Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\", \"checkpoint_path\": \"westd-30973:/root/symb_invariant_consensus/results/multi_seed/llama8b_pw_seed456_v2/\", \"wall_clock_seconds\": 51896.6, \"gpu_hours\": 14.42}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 71.67, \"sica_accuracy\": 66.17, \"delta\": -5.5, \"n\": 600}, \"completed_at\": \"2026-05-23T20:34:32.186Z\"}, \"exp-multi-seed-llama-pw-seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T04:43:53.558Z\", \"updated_at\": \"2026-05-23T20:16:30.026Z\", \"hypothesis\": \"LLaMA-3.1-8B PW seed789 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42/123/456 组成 4-seed 覆盖。\", \"parent\": \"exp-multi-seed-llama-pw\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8009 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/llama8b_pw_seed789/results.json\\\"\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:0\"], \"pid\": \"745722\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-llama-pw-seed789.log\", \"submitted_at\": \"2026-05-23T04:55:49.322Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\", \"wall_clock_seconds\": 55240.7, \"gpu_hours\": 15.34}, \"notes\": \"westd-16639 上的旧版本，已被 v2 (westd-30973) 取代。进程已不存在。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-23T20:16:30.026Z\"}, \"exp-multi-seed-qwen3-pw-seed789\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-23T20:14:49.190Z\", \"updated_at\": \"2026-05-23T20:15:24.607Z\", \"hypothesis\": \"Qwen3-14B non-thinking PW seed789 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。\", \"parent\": \"exp-027-qwen3-14b-non-thinking\", \"spec\": {\"command\": \"python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8022 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen3_pw_seed789/results.json\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:3\"], \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen3-14B\", \"eval_data\": \"data/proofwriter_full.json\"}}, \"exp-multi-seed-qwen3-pw-seed456\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-23T20:14:48.152Z\", \"updated_at\": \"2026-05-23T20:15:22.388Z\", \"hypothesis\": \"Qwen3-14B non-thinking PW seed456 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。\", \"parent\": \"exp-027-qwen3-14b-non-thinking\", \"spec\": {\"command\": \"python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8021 --seed 456 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen3_pw_seed456/results.json\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:2\"], \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 456, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen3-14B\", \"eval_data\": \"data/proofwriter_full.json\"}}, \"exp-multi-seed-qwen3-pw-seed123\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-23T20:14:46.739Z\", \"updated_at\": \"2026-05-23T20:15:20.125Z\", \"hypothesis\": \"Qwen3-14B non-thinking PW seed123 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。\", \"parent\": \"exp-027-qwen3-14b-non-thinking\", \"spec\": {\"command\": \"python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8020 --seed 123 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen3_pw_seed123/results.json\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 123, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen3-14B\", \"eval_data\": \"data/proofwriter_full.json\"}}, \"exp-092-llama8b-pw-nli-combo\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:37:55.376Z\", \"updated_at\": \"2026-05-23T12:40:13.698Z\", \"hypothesis\": \"LLaMA-3.1-8B ProofWriter NLI combo: DeBERTa-large-MNLI standalone (55%) < SC (70%)，capability gap = -15pp。验证 NLI combo 是否在第二个 model family 上也能提升 SC accuracy。\", \"parent\": \"exp-090-r-nli-proofwriter\", \"spec\": {\"command\": \"python scripts/exp092_llama8b_pw_nli_combo.py\", \"server\": \"westd-16639\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Meta-Llama-3.1-8B-Instruct + microsoft/deberta-large-mnli\", \"seed\": 42, \"checkpoint_path\": \"results/exp092_llama8b_pw_nli_combo/results.json\", \"log_path\": \"results/exp092_llama8b_pw_nli_combo/\", \"checkpoint_source\": \"exp048_llama8b_pw600 traces\", \"eval_data\": \"data/proofwriter_full.json (ProofWriter-D5 OWA, n=600)\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 0.7, \"nli_standalone\": 0.55, \"capability_gap_pp\": -15, \"combo_w1\": 0.7283, \"combo_w3\": 0.7417, \"combo_w5\": 0.7167, \"delta_w1_pp\": 2.83, \"delta_w3_pp\": 4.17, \"delta_w5_pp\": 1.67, \"mcnemar_w1_p\": 0.0001, \"mcnemar_w3_p\": 0.0035, \"mcnemar_w5_p\": 0.4335, \"nli_correct_sc_wrong\": 120, \"sc_correct_nli_wrong\": 210}, \"completed_at\": \"2026-05-20T22:38:31.288Z\", \"notes\": \"sc_baseline=0.70 uses Counter.most_common() tiebreaking; paper Table 3 uses alphabetical tiebreaking (SC=72.50%). See artifacts/table3_tiebreak_fix_report.md.\"}, \"exp-multi-seed-llama-pw-seed456\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-23T04:43:51.899Z\", \"updated_at\": \"2026-05-23T05:13:19.566Z\", \"hypothesis\": \"LLaMA-3.1-8B PW seed456 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42/123/789 组成 4-seed 覆盖。\", \"parent\": \"exp-multi-seed-llama-pw\"}, \"exp-multi-seed-qwen25-pw-seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T23:35:23.194Z\", \"updated_at\": \"2026-05-23T00:05:41.222Z\", \"hypothesis\": \"Qwen2.5-14B PW seed789 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性。Parent exp-multi-seed-qwen25 的 PW 部分补充。\", \"parent\": \"exp-multi-seed-qwen25\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_qwen25_pw_seed789_cuda2.sh\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:2\"], \"pid\": \"712285\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-qwen25-pw-seed789.log\", \"submitted_at\": \"2026-05-22T23:35:35.473Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\", \"wall_clock_seconds\": 889.8, \"gpu_hours\": 0.25}, \"conclusion\": \"failed\", \"notes\": \"全零结果：vLLM 未加载完就执行了脚本（30.2s 完成，正常需数小时）。代码路径错误（用了 run_full_mvp.py 而非 run_cross_dataset_replication.py）。seed789 将由 cuda:0 chain 自然执行。\", \"completed_at\": \"2026-05-22T23:50:25.264Z\"}, \"exp-multi-seed-mistral-pw\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T03:45:03.665Z\", \"updated_at\": \"2026-05-22T23:27:37.244Z\", \"hypothesis\": \"Multi-seed replication (seeds 42,123,456,789) of Mistral-7B × ProofWriter-600 shows consistent Δ(SICA-SC) direction across seeds, confirming single-seed results are not artifacts of random sampling. Addresses W4 reviewer concern about reproducibility.\", \"notes\": \"All 4 seeds completed on westd-16639 cuda:2. Wall time ~18h total (seed42 16:28→seed789 07:20 CST). 4/4 seeds Δ≤0, mean Δ=-2.38±1.12pp. SCB confirmed on Mistral×PW across all seeds.\", \"metrics\": {\"pw_seed42\": {\"sc_acc\": 40, \"sica_acc\": 36.67, \"delta\": -3.33, \"n\": 600, \"status\": \"COMPLETE\"}, \"pw_seed123\": {\"sc_acc\": 40.83, \"sica_acc\": 37.5, \"delta\": -3.33, \"n\": 600, \"status\": \"COMPLETE\"}, \"pw_seed456\": {\"sc_acc\": 39.83, \"sica_acc\": 38.67, \"delta\": -1.17, \"n\": 600, \"status\": \"COMPLETE\"}, \"pw_seed789\": {\"sc_acc\": 38.83, \"sica_acc\": 37.17, \"delta\": -1.67, \"n\": 600, \"status\": \"COMPLETE\"}, \"mean_4seed\": {\"sc\": 39.87, \"sc_sd\": 0.82, \"sica\": 37.5, \"sica_sd\": 0.85, \"delta\": -2.38, \"delta_sd\": 1.12, \"n_seeds\": 4, \"all_delta_leq_0\": true}}, \"checkpoint_path\": \"results/multi_seed/mistral_pw_seed{42,123,456,789}/results.json\", \"log_path\": \"/tmp/multiseed_mistral_pw_all.log\", \"conclusion\": \"success\", \"spec\": {\"command\": \"bash run_multiseed_mistral_pw.sh\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/\", \"data_count\": 600, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": \"42,123,456,789\"}, \"completed_at\": \"2026-05-22T23:27:37.244Z\"}, \"exp-deberta-ft-combo\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-22T18:54:25.357Z\", \"updated_at\": \"2026-05-22T19:36:59.517Z\", \"hypothesis\": \"Fine-tuned DeBERTa-large on ProofWriter OWA depth-5 achieves near-perfect NLI accuracy (99.67%) and provides massive combo gains over SC baseline when used as external verifier, demonstrating that domain-specific NLI fine-tuning breaks the SCB ceiling by providing truly independent verification signal.\", \"metrics\": {\"standalone_acc\": 99.67, \"standalone_n\": 600, \"errors\": 2, \"d061_corrected\": true, \"mistral\": {\"sc_baseline\": 39.17, \"w1\": {\"acc\": 42.33, \"delta\": 3.17, \"p\": \"<0.0001\"}, \"w3\": {\"acc\": 52.17, \"delta\": 13, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 65.5, \"delta\": 26.33, \"p\": \"<0.0001\"}, \"nli_up_sc_down\": 365, \"sc_up_nli_down\": 2}, \"llama8b\": {\"sc_baseline\": 72.5, \"w1\": {\"acc\": 76, \"delta\": 3.5, \"p\": \"<0.0001\"}, \"w3\": {\"acc\": 84.17, \"delta\": 11.67, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 91.67, \"delta\": 19.17, \"p\": \"<0.0001\"}, \"nli_up_sc_down\": 164, \"sc_up_nli_down\": 1}, \"qwen25_14b\": {\"sc_baseline\": 74, \"w1\": {\"acc\": 75, \"delta\": 1, \"p\": \"<0.05\"}, \"w3\": {\"acc\": 78.5, \"delta\": 4.5, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 83, \"delta\": 9, \"p\": \"<0.0001\"}}, \"qwen3_14b\": {\"sc_baseline\": 85.83, \"w1\": {\"acc\": 86.5, \"delta\": 0.67, \"p\": \"ns\"}, \"w3\": {\"acc\": 88, \"delta\": 2.17, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 90, \"delta\": 4.17, \"p\": \"<0.0001\"}}}, \"conclusion\": \"success\", \"notes\": \"D061 tiebreaking confirmed correct in eval_finetuned_nli.py. SC baselines recomputed from raw votes (not trace sc_answer). Paper SC values need updating: LLaMA 70.00→72.50%, Qwen2.5 73.50→74.00%, Mistral 39.33→39.17%. Root cause: traces sc_answer used max(dict_keys) = Unknown-first, D061 sorted()[0] = False-first. Combo JSON: /root/symb_invariant_consensus/artifacts/deberta_ft_combo_all.json\"}, \"exp-multi-seed-llama-pw\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T13:20:25.478Z\", \"updated_at\": \"2026-05-22T17:50:36.627Z\", \"hypothesis\": \"Multi-seed replication (seeds 42,123,456) of LLaMA-3.1-8B × ProofWriter-600 adds cross-dataset evidence for the third model family. If Δ(SICA-SC)≤0 holds on PW as well as FOLIO, it confirms SCB is dataset-invariant within LLaMA-8B. Addresses W4 reviewer concern.\", \"spec\": {\"command\": \"multiseed_llama8b_pw_cuda3.sh\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:3\"], \"pid\": \"614142\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-llama-pw.log\", \"submitted_at\": \"2026-05-22T13:22:26.637Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"ProofWriter-600\", \"data_count\": 600, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": \"42,123,456\", \"wall_clock_seconds\": 16090.0, \"gpu_hours\": 4.47}, \"notes\": \"disk full crash. Seed 42 crashed at 223/600. Seeds 123/456 not started. Recovery planned on westd-14391.\", \"metrics\": {\"pw_seed42\": {\"status\": \"running\", \"progress\": \"60/600\"}, \"pw_seed123\": {\"status\": \"pending\"}, \"pw_seed456\": {\"status\": \"pending\"}}, \"reproduce\": {\"finished_at\": \"2026-05-22T17:43:13.830Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-22T17:43:18.767541+00:00\"}]}, \"completed_at\": \"2026-05-22T17:50:36.627Z\"}, \"exp-multi-seed-llama-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T11:09:17.058Z\", \"updated_at\": \"2026-05-22T17:50:35.034Z\", \"hypothesis\": \"Multi-seed replication (seeds 123,456,789) of LLaMA-3.1-8B × FOLIO-204 shows consistent Δ(SICA-SC) direction across seeds, adding a third model family (beyond Qwen2.5 and Mistral) for cross-family consistency evidence. Addresses W4 reviewer concern.\", \"notes\": \"disk full crash. Seeds 123/456 completed (204/204). Seed 789 crashed at 189/204 — only 15 samples short. Recovery planned on westd-14391.\", \"metrics\": {\"seed123\": {\"sc_acc\": 67.16, \"sica_acc\": 63.73, \"delta\": -3.43, \"n\": 204, \"extraction_rate\": 0.959, \"status\": \"COMPLETE\"}, \"seed456\": {\"status\": \"running\", \"progress\": \"125/204\"}, \"seed789\": {\"status\": \"pending\"}}, \"reproduce\": {\"finished_at\": \"2026-05-22T17:43:01.884Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-22T17:43:10.456647+00:00\"}]}, \"spec\": {\"command\": \"multiseed_llama8b_folio_cuda1.sh\", \"server\": \"westd-16639\", \"data_path\": \"FOLIO-204\", \"data_count\": 204, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": \"123,456,789\"}, \"completed_at\": \"2026-05-22T17:50:35.034Z\"}, \"exp-multi-seed-mistral-folio\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-22T10:44:11.464Z\", \"updated_at\": \"2026-05-22T14:50:26.866Z\", \"hypothesis\": \"Multi-seed replication (seeds 123,456,789) of Mistral-7B × FOLIO-204 shows consistent Δ(SICA-SC) direction across seeds. Baseline seed=42 already available. Combined with Mistral×PW and Qwen2.5×FOLIO/PW multi-seed, provides comprehensive reproducibility evidence for W4 reviewer response.\", \"notes\": \"DATA AUDIT COMPLETE. multi_seed/seed123: SC=57.84% (differs from exp052 SC=53.92% by 4pp — different run, code version mismatch). multi_seed/seed456: CORRUPTED — vLLM crash, 111/204 empty problems, invalid. multi_seed/seed789: CLEAN — backup matches main, normal runtime 4798s. PAPER USES: exp052 (seed=123, D064-corrected SC=54.41%) + exp053 (seed=456, D064-corrected SC=55.88%) + PID 576938 seed=789 (SC=59.31%). Earlier report of 67.16% was LLaMA FOLIO seed=123 misattributed to Mistral.\", \"reproduce\": {\"finished_at\": \"2026-05-22T12:17:42.850Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-22T11:25:59.217138+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-22T12:17:49.422704+00:00\"}]}, \"metrics\": {\"d064_corrected\": true, \"seed123\": {\"sc_acc\": 54.41, \"sica_acc\": 57.35, \"delta\": 2.94, \"n\": 204, \"source\": \"exp052 D064-reeval\"}, \"seed456\": {\"sc_acc\": 55.88, \"sica_acc\": 55.88, \"delta\": 0, \"n\": 204, \"source\": \"exp053 D064-reeval\"}, \"seed789\": {\"sc_acc\": 59.31, \"sica_acc\": 56.86, \"delta\": -2.45, \"n\": 204, \"source\": \"PID 576938 (D064 built-in)\"}, \"mean_3seed\": {\"sc\": 56.53, \"sc_sd\": 2.51, \"sica\": 56.7, \"sica_sd\": 0.75, \"delta\": 0.16, \"delta_sd\": 2.7, \"n_seeds\": 3}}}, \"exp-multi-seed-qwen25-7b-folio\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-22T11:59:30.495Z\", \"updated_at\": \"2026-05-22T11:59:30.495Z\", \"hypothesis\": \"Multi-seed replication (seeds 123,456,789) of Qwen2.5-7B × FOLIO-204 adds a fourth model family (beyond Qwen2.5-14B, Mistral-7B, LLaMA-8B) for cross-family consistency of SCB. If Δ(SICA-SC)≤0 holds across 7B-scale Qwen as well, it strengthens the scale+architecture invariance claim.\"}, \"exp-multi-seed-qwen25\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-22T03:45:39.066Z\", \"updated_at\": \"2026-05-22T11:19:38.047Z\", \"hypothesis\": \"Multi-seed replication (seeds 123,456,789) of Qwen2.5-14B × FOLIO-204 and ProofWriter-600 shows consistent Δ(SICA-SC) direction across seeds. Baseline seed=42: FOLIO Δ=-1.96pp, PW Δ=-2.00pp. Addresses W4 reviewer concern.\", \"notes\": \"FOLIO 4-seed COMPLETE (guard killed cuda:1 master PID 510872 as designed). Cron auto-resolved DONE(failed) is misleading — FOLIO portion is success. PW 3-seed still running on cuda:0 PID 552333 (independent process, not tracked by this cron). FOLIO results: mean Δ=-1.24±0.86pp, 4/4 seeds ≤0.\", \"metrics\": {\"folio_seed42\": {\"sc_acc\": 77.5, \"sica_acc\": 75.49, \"delta\": -2.01, \"n\": 204, \"source\": \"baseline\"}, \"folio_seed123\": {\"sc_acc\": 74.51, \"sica_acc\": 73.04, \"delta\": -1.47, \"n\": 204}, \"folio_seed456\": {\"sc_acc\": 74.02, \"sica_acc\": 74.02, \"delta\": 0, \"n\": 204}, \"folio_seed789\": {\"sc_acc\": 74.02, \"sica_acc\": 72.55, \"delta\": -1.47, \"n\": 204, \"status\": \"FINAL\"}, \"folio_mean\": {\"sc\": 75.01, \"sica\": 73.78, \"delta\": -1.24, \"sc_sd\": 1.67, \"sica_sd\": 1.3, \"delta_sd\": 0.86, \"n_seeds\": 4}, \"pw_seed123\": {\"status\": \"running\", \"progress\": \"190/600\", \"pid\": 552333, \"gpu\": \"cuda:0\"}, \"pw_seed456\": {\"status\": \"pending\", \"note\": \"directory has garbage from cuda:1 (max_model_len bug), cuda:0 will overwrite\"}, \"pw_seed789\": {\"status\": \"pending\"}, \"pw_eta\": \"2026-05-23T17:40Z\"}, \"reproduce\": {\"finished_at\": \"2026-05-22T11:19:15.466Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-22T11:19:27.365730+00:00\"}]}}, \"exp-013-constraint-ablation\": {\"status\": \"PREPARING\", \"retry_count\": 1, \"created_at\": \"2026-05-20T00:08:40.394Z\", \"updated_at\": \"2026-05-22T08:20:31.018Z\", \"hypothesis\": \"MaxSAT satisfiability checking contributes minimal accuracy gains over naive constraint counting, because extracted constraints are too homogeneous (trace co-sourcing) to provide discriminative satisfiability signals. If SICA-MaxSAT ≈ SICA-count-only, the SAT solver is not the bottleneck — constraint quality is.\", \"completed_at\": \"2026-05-20T00:09:26.321Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"maxsat_acc\": 0.4229, \"count_only_acc\": 0.4216, \"random_weight_acc\": \"0.4206±0.0042\", \"sc_acc\": 0.4316, \"delta_maxsat_vs_countonly_pp\": 0.12, \"delta_maxsat_vs_sc_pp\": -0.87, \"agreement_maxsat_countonly\": 0.944, \"n_problems\": 804, \"folio_maxsat\": 0.5931, \"folio_count\": 0.5686, \"folio_sc\": 0.5441, \"pw_maxsat\": 0.365, \"pw_count\": 0.3717, \"pw_sc\": 0.3933}}}, \"metrics\": {\"alpha_ablation\": {\"mistral_folio\": {\"alpha_0.1\": {\"sica_acc\": 54.9, \"countonly_acc\": 54.9, \"agreement\": 100}, \"alpha_0.3\": {\"sica_acc\": 54.9, \"countonly_acc\": 54.9, \"agreement\": 100}, \"alpha_0.5\": {\"sica_acc\": 54.9, \"countonly_acc\": 54.9, \"agreement\": 100}, \"alpha_0.7\": {\"sica_acc\": 53.92, \"countonly_acc\": 54.41, \"agreement\": 99}, \"alpha_0.9\": {\"sica_acc\": 54.9, \"countonly_acc\": 55.39, \"agreement\": 99}}, \"qwen25_folio\": {\"alpha_0.1\": {\"sica_acc\": 75, \"countonly_acc\": 75, \"agreement\": 100}, \"alpha_0.3\": {\"sica_acc\": 75, \"countonly_acc\": 75, \"agreement\": 100}, \"alpha_0.5\": {\"sica_acc\": 75, \"countonly_acc\": 75, \"agreement\": 100}, \"alpha_0.7\": {\"sica_acc\": 74.51, \"countonly_acc\": 74.51, \"agreement\": 100}, \"alpha_0.9\": {\"sica_acc\": 74.02, \"countonly_acc\": 74.02, \"agreement\": 100}}, \"conclusion\": \"Agreement >= 99% across all alpha for both conditions. MAX-SAT equiv count-only is alpha-insensitive.\"}}, \"conclusion\": \"success\", \"notes\": \"V16 rerun with correct Qwen2.5-14B (exp036+exp032) and R1-Distill-8B data. MaxSAT ≈ count-only or worse. Strongly supports SCB narrative: constraints vote, not reason. Random-weight -6.4pp confirms count structure matters but SAT solving adds nothing.\"}, \"exp-folio-2x2-crossmodel\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T23:04:53.974Z\", \"updated_at\": \"2026-05-22T05:34:00.507Z\", \"hypothesis\": \"Cross-model extraction on FOLIO-204 replicates ProofWriter 2×2 finding: extractor capability dominates SICA accuracy regardless of generator, and BR>1 persists in all cells. If confirmed, this generalizes the SCB universality + extractor dominance finding across two distinct reasoning datasets.\", \"parent\": \"exp-d126-crossmodel-sica\", \"notes\": \"FOLIO 2×2 completed. All 4 cells 204 items. Sentinel found. BR>1 all cells (1.94-2.70). Qwen3 ext improves Mistral gen by +3.92pp but Mistral ext reduces Qwen3 gen by -1.47pp. McNemar p≈0 both directions. Results saved: folio_2x2_metrics.json. Log: master.log. Checkpoint: results/exp_folio_2x2/\", \"conclusion\": \"success\", \"metrics\": {\"folio_2x2\": {\"mistral_gen_mistral_ext\": {\"SICA\": 56.86, \"delta_pp\": 0.98, \"BR_mean\": 2.7}, \"mistral_gen_qwen3_ext\": {\"SICA\": 59.8, \"delta_pp\": 3.92, \"BR_mean\": 1.94}, \"qwen3_gen_mistral_ext\": {\"SICA\": 81.86, \"delta_pp\": -1.47, \"BR_mean\": 2.66}, \"qwen3_gen_qwen3_ext\": {\"SICA\": 84.8, \"delta_pp\": 1.47, \"BR_mean\": 2.35}}, \"SC_mistral\": 55.88, \"SC_qwen3\": 83.33, \"kappa_mistral\": 0.46, \"kappa_qwen3\": 0.79, \"mcnemar_mistral_ext_p\": 0, \"mcnemar_qwen3_ext_p\": 0}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp_folio_2x2/folio_2x2_metrics.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp_folio_2x2/master.log\", \"completed_at\": \"2026-05-22T05:34:00.507Z\"}, \"exp-d126-70b-sica\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:01:56.827Z\", \"updated_at\": \"2026-05-22T02:08:10.449Z\", \"hypothesis\": \"Symbolic confirmation bias persists at 72B scale: Qwen2.5-72B self-extracted constraints will show BR > 1 and κ ≥ 0.40, with SICA ≈ SC (no significant improvement), demonstrating that the independence bottleneck is scale-invariant beyond the 7B-14B range tested so far.\", \"notes\": \"westd-16639 单卡 70B (PID 436077) 已被 D136 主动终止（25/204, ETA 45h 不经济）。实验转移到 westd-25068 tp=4 (PID 40007, vLLM PID 39013 port 8002, AWQ 39GB confirmed)。westd-25068 进度 52/204, ETA ~2.6h, avg 61.8s/prob。folio_0-folio_11 (12题) 在 westd-25068 标为 SKIPPED，合并时需用 westd-16639 实际结果替换。\", \"reproduce\": {\"finished_at\": \"2026-05-21T19:46:11.474Z\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T19:46:22.575967+00:00\"}]}, \"spec\": {\"command\": \"python exp_70b_sica_awq_25068.py\", \"server\": \"westd-25068\", \"data_path\": \"folio_12 (204 problems)\", \"data_count\": 204, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42}, \"completed_at\": \"2026-05-22T02:08:10.449Z\"}, \"exp-d126-crossmodel-sica\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:01:59.598Z\", \"updated_at\": \"2026-05-21T22:22:32.773Z\", \"hypothesis\": \"Cross-model constraint extraction (Generator: Qwen3-14B, Extractor: Mistral-7B, and vice versa) reduces symbolic confirmation bias compared to same-model extraction. If SCB stems from same-model distributional overlap, cross-model extraction should lower BR and improve SICA accuracy on ProofWriter N=204.\", \"notes\": \"2×2 cross-model SICA completed 05:39 UTC. SCB universality confirmed, extractor dominance as key finding (D140). Cron auto-fail was false alarm — process exited normally after completion. 2×2 matrix: Qwen3 ext ~79.9% regardless of generator, Mistral ext 34-38%. BR>1 all 4 cells. Process-κ generator-intrinsic. JSON: crossmodel_2x2_metrics.json\", \"metrics\": {\"2x2_matrix\": {\"mistral_gen_mistral_ext\": {\"SICA\": 34.31, \"delta_pp\": -5.88, \"BR_mean\": 3.44, \"BR_inf_rate\": 32.1, \"process_kappa\": 0.619}, \"mistral_gen_qwen3_ext\": {\"SICA\": 79.9, \"delta_pp\": 39.71, \"BR_mean\": 2.85, \"BR_inf_rate\": 17.1, \"process_kappa\": 0.619}, \"qwen3_gen_mistral_ext\": {\"SICA\": 37.75, \"delta_pp\": -49.02, \"BR_mean\": 2.16, \"BR_inf_rate\": 45.7, \"process_kappa\": 0.836}, \"qwen3_gen_qwen3_ext\": {\"SICA\": 79.9, \"delta_pp\": -6.86, \"BR_mean\": 1.16, \"BR_inf_rate\": 63.4, \"process_kappa\": 0.836}}, \"SC_mistral\": 40.2, \"SC_qwen3\": 86.8, \"key_finding\": \"Extractor capability dominates SICA accuracy; BR>1 in all 4 cells confirming SCB universality\"}, \"conclusion\": \"success\", \"reproduce\": {\"finished_at\": \"2026-05-21T22:20:31.518Z\"}, \"failure_reason\": \"N/A — cron false alarm, experiment completed successfully via workers (not training job)\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T22:20:36.451925+00:00\"}]}, \"completed_at\": \"2026-05-21T22:21:56.648Z\", \"checkpoint_path\": \"N/A (data collection experiment, no checkpoint)\", \"log_path\": \"N/A (data collection via workers, no training log)\"}, \"exp-d135-frontier-scb\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T13:52:18.586Z\", \"updated_at\": \"2026-05-21T21:58:27.253Z\", \"hypothesis\": \"2026 frontier closed-source models (Claude/GPT/Gemini via OpenRouter) also exhibit SCB: self-extracted constraints will show BR≥2× with SICA≈SC, extending the scale-invariance finding from open-source 7B-72B to frontier closed-source models.\", \"notes\": \"Multi-model frontier SCB experiment, still active. Cron false alarm: tracked PID 473361 (o3 extraction, completed 196/196), auto-failed on 5th dead check — reverted to PREPARING. Active sub-experiments: exp-d126-70b-sica (70B AWQ tp=4, westd-25068), exp-d126-crossmodel-sica (cross-model 2×2, westd-16639). Gemini SC running via API (westd-25068). Completed sub-components: gpt-4o ✅, gpt-4.1 ✅, gpt-5.5 ✅, o3 extraction ✅, R1-Distill ✅.\", \"metrics\": {\"gpt4o_self\": {\"SC\": 73.9, \"SICA\": 72.1, \"BR_mean\": 2.94, \"process_kappa\": 0.79, \"answer_kappa\": 0.8}, \"gpt41_cross_mistral\": {\"SC\": 82.84, \"SICA\": 81.37, \"delta_pp\": -1.47, \"BR_mean\": 2.7, \"process_kappa\": 0.79, \"answer_kappa\": 0.86}, \"gpt55_cross_mistral\": {\"SC\": 84.31, \"SICA\": 84.8, \"delta_pp\": 0.49, \"BR_mean\": 3.48, \"process_kappa\": 0.56, \"answer_kappa\": 0.96}, \"r1distill_cross_mistral\": {\"SC\": 74.51, \"SICA\": 76.96, \"delta_pp\": 2.45, \"BR_mean\": 2.92, \"process_kappa\": 0.25, \"answer_kappa\": 0.69}, \"o3_cross_mistral\": {\"SC\": 82.65, \"SICA\": 82.65, \"delta_pp\": 0, \"BR_mean\": 1.66, \"process_kappa\": 0.6, \"answer_kappa\": 0.92}, \"gemini_interim_95q\": {\"SC\": 87.4, \"cross_SICA\": 86.3, \"delta_pp\": -1.1, \"process_kappa\": 0.79, \"n_questions\": 95, \"status\": \"extraction_complete_95q\"}}, \"reproduce\": {\"finished_at\": \"2026-05-21T19:23:45.838Z\"}, \"failure_reason\": \"FALSE ALARM: cron tracked completed o3 extraction PID 473361, auto-failed on 5th miss. Experiment is multi-component umbrella — active sub-experiments continue under separate exp_ids.\", \"conclusion\": \"failed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T17:01:28.722448+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T19:23:50.624203+00:00\"}]}}, \"exp-text-ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:17:46.811Z\", \"updated_at\": \"2026-05-21T18:07:10.870Z\", \"hypothesis\": \"Constraint extraction temperature (T_ext) affects SICA accuracy: moderate T_ext (0.3-0.5) produces more diverse yet valid constraints than extremes (0.1 too deterministic, 1.0 too noisy), yielding higher SICA-SC delta on FOLIO-204.\", \"spec\": {\"command\": \"python /root/symb_invariant_consensus/ablation_text.py\", \"server\": \"westd-25068\", \"data_path\": \"results/exp033_mistral_7b_folio204/intermediates/\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"results/ablation_text/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T18:07:10.870Z\"}, \"exp-d126-r1-distill-sica\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T13:19:19.126Z\", \"updated_at\": \"2026-05-21T17:53:59.782Z\", \"hypothesis\": \"Reasoning-distilled model (DeepSeek-R1-Distill-LLaMA-8B) does not escape SCB: self-extracted constraints will show BR≥2× and SICA≈SC, demonstrating that SCB is a structural property of autoregressive self-extraction that reasoning training cannot eliminate.\", \"notes\": \"Pipeline re-run PID 451580: 130/204 intermediates, ETA ~17:10 UTC. Cross-extraction v2 has 93/204. Plan: pipeline finishes → kill R1-Distill vLLM (cuda:3) → deploy Mistral port 8004 → run reextract_bpe_fix.py for remaining ~111 problems → merge 204 → compute full SICA+BR+κ. Mistral model: /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3\", \"reproduce\": {\"finished_at\": \"2026-05-21T17:22:50.819Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T15:27:22.742934+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T17:22:59.657161+00:00\"}]}, \"metrics\": {\"cross_model_extraction_93\": {\"n_problems\": 93, \"sc_accuracy\": 0.7527, \"sica_accuracy\": 0.7849, \"delta_pp\": 3.22, \"mean_br\": 2.97, \"median_br\": 2, \"process_kappa_tfidf\": 0.2386, \"answer_fleiss_kappa\": 0.703, \"extractor\": \"Mistral-7B\"}, \"cross_model_extraction_204\": {\"n_problems\": 204, \"sc_accuracy\": 0.7451, \"sica_accuracy\": 0.7647, \"delta_pp\": 1.96, \"extraction_rate\": 0.933, \"total_constraints\": 14602, \"unique_constraints\": 8653, \"mean_br\": 2.85, \"median_br\": 2, \"process_kappa_tfidf\": 0.2477, \"answer_fleiss_kappa\": 0.6944, \"extractor\": \"Mistral-7B\", \"note\": \"Full 204 questions. Cross-model: R1-Distill traces extracted by Mistral-7B. BPE fix applied.\"}}}, \"exp-d134-e6-closed-model\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T09:01:38.677Z\", \"updated_at\": \"2026-05-21T14:53:24.439Z\", \"hypothesis\": \"Closed-source frontier models (GPT-4o, Claude, etc.) also exhibit symbolic confirmation bias when self-extracting FOL constraints. If SCB persists at frontier scale with different architectures, this strengthens the claim that SCB is a fundamental property of self-verification rather than a scale or architecture artifact.\", \"notes\": \"Partial run: 154/204 (75.5%). SICA=71.4%, SC=73.4%. Process exited without error at problem 155. Per-class SICA/SC: True 94.8%/93.1%, False 82.9%/82.9%, Unknown 38.2%/45.5%. 9 SICA-SC disagreements (SC wins 5, SICA wins 2).\", \"conclusion\": \"success\", \"metrics\": {\"gpt4o_folio\": {\"completed\": 161, \"total\": 204, \"sc_accuracy\": 0.7391, \"sica_accuracy\": 0.7205, \"delta_pp\": -1.86, \"n_sica_wrong\": 45, \"mean_br\": 2.94, \"median_br\": 1.91, \"weighted_br\": 3.07, \"n_br_finite\": 25, \"n_br_infinite\": 20, \"process_kappa_tfidf\": 0.7884, \"answer_fleiss_kappa\": 0.8009}}}, \"exp-d134-cil\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:21:06.301Z\", \"updated_at\": \"2026-05-21T10:22:07.111Z\", \"hypothesis\": \"CIL (Cumulative Information Lift) unifies combo gain prediction: CIL>0 iff verifier adds independent signal beyond generator. Cross-architecture NLI pairs show CIL>0 (predicting significant combo gain), while same-model SICA shows CIL≈0 (predicting no gain), validating CIL as the mechanistic criterion for escape.\", \"conclusion\": \"success\", \"metrics\": {\"n_pairs_computed\": 8, \"n_pairs_missing\": 2, \"spearman_rho\": 0.881, \"spearman_p\": 0.0039, \"pearson_r\": 0.8481, \"pearson_p\": 0.0078, \"cil_deberta_mistral_pw\": 1.67, \"cil_sica_mistral_pw\": -4.61, \"cil_deberta_qwen14b_pw\": -0.21, \"cil_sica_qwen14b_pw\": -4.21, \"corrected_v2\": \"Qwen14B canonical SC=74.00% (exp032). Gains: DeBERTa +0.33pp, SICA -2.50pp. Spearman 0.881 p=0.004.\"}}, \"exp-d134-baf-decoupled\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:21:08.341Z\", \"updated_at\": \"2026-05-21T09:07:43.966Z\", \"hypothesis\": \"Truncating CoT traces before the answer sentence reduces SCB: truncated-trace BR < full-trace BR, because answer leakage into FOL constraints is the primary SCB mechanism (Dir-H provenance showed late-step leakage 27.23% >> early 22.00%).\", \"conclusion\": \"negative\", \"metrics\": {\"full_trace_acc\": 0.5931, \"conservative_acc\": 0.5392, \"standard_acc\": 0.5441, \"aggressive_acc\": 0.5392, \"conservative_br_delta\": -0.049, \"conservative_wilcoxon_p\": 0.122, \"conservative_mcnemar_p\": 0.001, \"aggressive_br_delta\": -0.145, \"aggressive_wilcoxon_p\": 0.256, \"aggressive_mcnemar_p\": 0.013}}, \"exp-d134-process-br\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:21:03.003Z\", \"updated_at\": \"2026-05-21T09:07:36.544Z\", \"hypothesis\": \"SCB concentrates in late-step/answer-adjacent constraints: BR(late-step) >> BR(early-step), and BR(hard questions SC≤6/12) >> BR(easy questions SC≥10/12). If confirmed, SCB is driven by answer leakage into constraint extraction rather than uniform distributional bias.\", \"conclusion\": \"success\", \"metrics\": {\"position_br_early\": 5.37, \"position_br_mid\": 5.25, \"position_br_late\": 5.16, \"fisher_early_vs_late_p\": 0.708, \"difficulty_br_easy\": 18.82, \"difficulty_br_hard\": 2.71, \"fisher_diff_p\": 0, \"conditional_br\": 5.69, \"other_br\": 4.91, \"fisher_type_p\": 0.061}}, \"exp-d126-drc-folio\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:02:01.252Z\", \"updated_at\": \"2026-05-21T09:02:59.395Z\", \"hypothesis\": \"DRC (Disagreement-Routed Cascade) with DeBERTa NLI verification on FOLIO-204 recovers ≥80% of full NLI combo gain at ≤50% verification cost, extending the ProofWriter DRC result to a second dataset and demonstrating the generality of disagreement-based routing.\", \"conclusion\": \"success\", \"metrics\": {\"sc_acc\": 55.88, \"full_combo_w3_acc\": 58.82, \"drc_tau07_w3_acc\": 58.33, \"drc_tau07_gain_pp\": 2.45, \"drc_tau07_nli_calls\": \"71/204\", \"drc_tau07_cost_pct\": 34.8, \"drc_tau07_gain_recovery_pct\": 83.3, \"drc_tau08_w3_acc\": 58.82, \"drc_tau08_gain_recovery_pct\": 100, \"drc_tau08_cost_pct\": 48.5}}, \"exp_text_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:25:46.771Z\", \"updated_at\": \"2026-05-21T06:41:41.927Z\", \"hypothesis\": \"Constraint extraction temperature (T_ext) does not significantly affect SICA accuracy because confirmation bias is inherent to self-extraction regardless of temperature — constraints at any T_ext will project the model's distributional bias rather than provide independent verification signal\", \"spec\": {\"command\": \"python text_ablation.py --t_ext 0.1 0.5 0.7 1.0 --k 12 --T 0.7\", \"server\": \"westd-25068\", \"data_path\": \"FOLIO validation set\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct\", \"seed\": 42, \"pid\": 452128}, \"conclusion\": \"success\", \"metrics\": {\"t_ext_0.1\": {\"sica_acc\": 57.35, \"delta_pp\": 1.47, \"p\": 0.581}, \"t_ext_0.3\": {\"sica_acc\": 59.31, \"delta_pp\": 4.9, \"p\": 0.013}, \"t_ext_0.5\": {\"sica_acc\": 56.37, \"delta_pp\": 0.49, \"p\": 1}, \"t_ext_0.7\": {\"sica_acc\": 53.43, \"delta_pp\": -2.45, \"p\": 0.302}, \"t_ext_1.0\": {\"sica_acc\": 55.39, \"delta_pp\": -0.49, \"p\": 1}, \"sc_baseline\": 55.88}, \"log_path\": \"/root/symb_invariant_consensus/results/text_ablation.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/text_ablation_results.json\", \"completed_at\": \"2026-05-21T06:41:41.927Z\"}, \"exp-091-qwen14b-pw-nli-combo\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:43:24.690Z\", \"updated_at\": \"2026-05-20T21:44:03.847Z\", \"hypothesis\": \"Qwen2.5-14B ProofWriter NLI combo: DeBERTa-large-MNLI standalone (55%) < SC (73.50%)，capability gap = -18.50pp。根据 Push A capability gap 单调关系，combo gain 应介于 Qwen3 (+1.83pp) 和 Mistral (+10.67pp) 之间。\", \"parent\": \"exp-090-r-nli-proofwriter\", \"spec\": {\"command\": \"python direction_r_deberta_qwen14b_pw.py\", \"server\": \"westd-16639\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct + microsoft/deberta-large-mnli\", \"seed\": 42, \"checkpoint_path\": \"results/qwen14b_pw_nli_combo/results.json\", \"log_path\": \"results/qwen14b_pw_nli_combo/\", \"checkpoint_source\": \"exp046_qwen14b_pw600 traces\", \"eval_data\": \"data/proofwriter_full.json (ProofWriter-D5 OWA, n=600)\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 0.735, \"nli_standalone\": 0.55, \"capability_gap_pp\": -18.5, \"combo_w1\": 0.7417, \"combo_w3\": 0.7433, \"combo_w5\": 0.7533, \"delta_w1_pp\": 0.67, \"delta_w3_pp\": 0.83, \"delta_w5_pp\": 1.83, \"mcnemar_w1_p\": 0.344, \"mcnemar_w3_p\": 0.405, \"mcnemar_w5_p\": 0.144}, \"completed_at\": \"2026-05-20T21:44:03.847Z\"}, \"exp-wave3-dir-g-decoupling\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:20:09.909Z\", \"updated_at\": \"2026-05-20T20:55:51.195Z\", \"hypothesis\": \"Decoupling: 将 FOL 约束提取与答案生成解耦——先生成答案 trace，再独立提取 FOL 约束（不暴露答案给约束提取 prompt），可以打破 confirmation bias 因果链。Conservative 策略：截断 trace 中答案相关内容后再提取约束。\", \"spec\": {\"command\": \"python -u direction_g_decoupling.py --data data/folio_full.json --traces-dir results/exp033_mistral_folio204/ --output results/direction_g_decoupling/results.json\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_baseline\": 0.5441, \"sc_correct\": 111, \"sica_original\": 0.5931, \"sica_correct\": 121, \"conservative_accuracy\": 0.5392, \"conservative_correct\": 110, \"conservative_avg_trunc_pct\": 4.3, \"conservative_match_pct\": 98.4, \"standard_accuracy\": 0.5441, \"standard_correct\": 111, \"standard_avg_trunc_pct\": 18.9, \"standard_match_pct\": 98.4, \"aggressive_accuracy\": 0.5392, \"aggressive_correct\": 110, \"aggressive_avg_trunc_pct\": 35.3, \"aggressive_match_pct\": 100, \"best_strategy\": \"standard\", \"best_delta_vs_sc_pp\": 0, \"best_delta_vs_sica_pp\": -4.9}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/direction_g_decoupling/\", \"log_path\": \"/tmp/direction_g_full.log\", \"completed_at\": \"2026-05-20T20:55:51.195Z\"}, \"exp-090-r-nli-proofwriter\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T13:51:31.310Z\", \"updated_at\": \"2026-05-20T14:09:41.762Z\", \"hypothesis\": \"Cross-architecture NLI verification (DeBERTa-large-MNLI) 在 ProofWriter-D5 上也能提升 SC accuracy，验证 FOLIO 上 R 方法的跨数据集泛化能力。来源: R5-N4 审稿修复 + Claim 1 (cross-architecture escape generalization)。\", \"parent\": \"exp-wave3-dir-r-nli-verifier\", \"spec\": {\"command\": \"python3 direction_r_deberta_proofwriter.py\", \"server\": \"westd-25068\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"microsoft/deberta-large-mnli\", \"seed\": 42, \"checkpoint_path\": \"results/direction_r_nli_pw600/\", \"log_path\": \"/tmp/sf2_proofwriter_nli.log\", \"checkpoint_source\": \"exp046_mistral_7b_pw600\", \"eval_data\": \"data/proofwriter_full.json (ProofWriter-D5 OWA, n=600)\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 0.3933, \"sica_accuracy\": 0.365, \"nli_standalone\": 0.55, \"combo_w1\": 0.4017, \"combo_w3\": 0.4283, \"combo_w5\": 0.5, \"delta_w1_pp\": 0.83, \"delta_w3_pp\": 3.5, \"delta_w5_pp\": 10.67, \"mcnemar_w1_p\": 0.2668, \"mcnemar_w1_b\": 4, \"mcnemar_w1_c\": 9, \"mcnemar_w3_p\": 0.0125, \"mcnemar_w3_b\": 22, \"mcnemar_w3_c\": 43, \"mcnemar_w5_p\": 0.0001, \"mcnemar_w5_b\": 35, \"mcnemar_w5_c\": 99, \"nli_true_acc\": 0.64, \"nli_false_acc\": 0.975, \"nli_unknown_acc\": 0.035, \"nli_correct_sc_wrong\": 274, \"sc_correct_nli_wrong\": 180, \"agreement_acc\": 0.808}, \"completed_at\": \"2026-05-20T14:09:41.762Z\"}, \"exp-089-oracle-mistral-7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T13:34:37.133Z\", \"updated_at\": \"2026-05-20T13:35:27.948Z\", \"hypothesis\": \"Mistral-7B的oracle SICA（用FOLIO gold FOL替换自提取FOL）ceiling gap应显著大于Qwen-14B的+14.22pp，因为更弱模型的自提取FOL质量更差，gold FOL替换带来的提升更大。\", \"parent\": \"exp-oracle-folio\", \"spec\": {\"command\": \"python3 scripts/run_exp089_oracle_folio_mistral7b.py\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_path\": \"results/oracle_folio_mistral7b/\", \"log_path\": \"results/oracle_folio_mistral7b/\", \"checkpoint_source\": \"exp033_mistral_7b_folio204\", \"eval_data\": \"data/folio_full.json (gold FOL annotations)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T13:35:22.766Z\", \"metrics\": {\"sc_accuracy\": 0.5588, \"oracle_sica_accuracy\": 0.8578, \"sica_self_accuracy\": 0.5931, \"delta_oracle_sc_pp\": 29.9, \"delta_oracle_sica_pp\": 26.47, \"mcnemar_oracle_vs_sc_p\": 9.99e-14, \"mcnemar_oracle_vs_sc_b\": 63, \"mcnemar_oracle_vs_sc_c\": 2, \"mcnemar_oracle_vs_sica_p\": 7.84e-12, \"mcnemar_oracle_vs_sica_b\": 57, \"mcnemar_oracle_vs_sica_c\": 3, \"z3_gold_agreement\": 0.951, \"fol_parse_success\": 1, \"oracle_true_acc\": 0.875, \"oracle_false_acc\": 0.778, \"oracle_unknown_acc\": 0.913, \"n\": 204, \"utilization_pct\": 11.5}}, \"exp-wave3-dir-r-nli-verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:54:26.690Z\", \"updated_at\": \"2026-05-20T12:17:08.499Z\", \"hypothesis\": \"DeBERTa External Verifier: encoder-only NLI 模型 (cross-encoder/nli-deberta-v3-base) 与 decoder-only LLM 架构独立，作为额外 vote 加入 SC traces 可打破 confirmation bias。NLI 擅长 contradiction 检测（False label），LLM 擅长 Unknown 推理，两者互补。\", \"spec\": {\"command\": \"python direction_r_nli_verifier.py --model cross-encoder/nli-deberta-v3-base --data data/folio_full.json --traces-dir results/exp033_mistral_folio204/ --output results/direction_r_nli_small/results.json\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"cross-encoder/nli-deberta-v3-base + Mistral-7B-Instruct-v0.3 SC traces\", \"seed\": 42, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/direction_r_nli_small/results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/direction_r_nli_large/\"}, \"metrics\": {\"sc_accuracy\": 0.5441, \"nli_standalone\": 0.4951, \"combo_w1\": 0.5784, \"combo_w3\": 0.5882, \"intersection_acc\": 0.6848, \"intersection_coverage\": 0.451, \"delta_w1_pp\": 3.43, \"delta_w3_pp\": 4.41, \"mcnemar_w1_p\": 0.0391, \"mcnemar_w1_b\": 1, \"mcnemar_w1_c\": 8, \"mcnemar_w3_p\": 0.0784, \"mcnemar_w3_b\": 6, \"mcnemar_w3_c\": 15, \"ci95_w1\": [0.98, 6.37], \"ci95_w3\": [0, 8.82], \"nli_false_acc\": 0.7143, \"sc_false_acc\": 0.381, \"nli_unknown_acc\": 0.1884, \"sc_unknown_acc\": 0.6812, \"model_nli\": \"microsoft/deberta-large-mnli\", \"n\": 204}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T11:50:51.231Z\"}, \"exp-wave3-dir-r-combo-extended\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:52:56.684Z\", \"updated_at\": \"2026-05-20T11:53:26.968Z\", \"hypothesis\": \"R combo 策略扩展：测试 NLI 作为不同权重投票（w=1/3/5）、intersection+fallback、cascade（按 NLI confidence 分流）、weighted averaging 等策略。寻找 NLI+SICA/SC 最优融合方式。\", \"spec\": {\"command\": \"python direction_rg_combo.py\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"deberta-large-mnli + Mistral-7B SC traces + SICA\", \"seed\": 42, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/direction_rg_combo/results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/direction_rg_combo/\"}, \"conclusion\": \"success\", \"metrics\": {\"sc_accuracy\": 0.5441, \"sica_accuracy\": 0.5931, \"nli_standalone\": 0.4951, \"best_combo\": \"nli_sc_vote_w5\", \"best_combo_acc\": 0.6029, \"best_delta_sc_pp\": 5.88, \"best_delta_sica_pp\": 0.98, \"nli_sc_vote_w3\": 0.5882, \"intersection_sica_fallback\": 0.5931, \"intersection_sc_fallback\": 0.5735, \"oracle_upper_bound\": 0.7549, \"sica_nli_agreement\": 0.475, \"agreement_accuracy\": 0.701, \"n\": 204}, \"completed_at\": \"2026-05-20T11:53:26.969Z\"}, \"exp-wave3-dir-k-minority\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:30:03.741Z\", \"updated_at\": \"2026-05-20T10:30:42.427Z\", \"hypothesis\": \"Minority Report: 当 SICA 错误时，少数派 traces 可能更 consistent（Z3 约束内部自洽性更高）。如果少数派 consistency > 多数派，用 consistency-weighted voting 替代 majority vote 可以纠正部分错误。测试 strict/moderate/combined 三种策略。\", \"spec\": {\"command\": \"python direction_k_minority_report.py --data data/folio_full.json --traces-dir results/exp033_mistral_folio204/ --output results/direction_k_minority_report/results.json\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/direction_k_minority_report/results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/direction_k_minority_report/\"}, \"metrics\": {\"sc_accuracy\": 0.5441, \"strict_accuracy\": 0.5441, \"strict_delta_pp\": 0, \"moderate_accuracy\": 0.4951, \"moderate_delta_pp\": -4.9, \"combined_accuracy\": 0.5441, \"combined_delta_pp\": 0, \"minority_consistency_precision\": 0.3553, \"minority_gt_rate\": 0.3373, \"majority_gt_rate\": 0.488, \"moderate_flips\": 76, \"moderate_correct_flips\": 27, \"moderate_wrong_flips\": 49, \"n\": 204}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T10:30:42.427Z\"}, \"exp-wave3-dir-i-z3-filter\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:23:12.344Z\", \"updated_at\": \"2026-05-20T09:25:19.523Z\", \"hypothesis\": \"Z3 Trace Filter: Per-trace FOL constraint set SAT/UNSAT check can identify internally contradictory traces; filtering them before SC voting will improve accuracy by removing logically flawed reasoning.\", \"spec\": {\"command\": \"python direction_i_z3_filter.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 SICA constraints\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_baseline\": 54.41, \"filtered_sc\": 53.92, \"delta_pp\": -0.49, \"unsat_traces\": 142, \"unsat_rate_pct\": 5.8, \"filter_precision_pct\": 49.12, \"questions_affected\": 7, \"improved\": 3, \"degraded\": 4}, \"checkpoint_path\": \"westd-25068:/root/symb_invariant_consensus/results/direction_i_z3_filter/results.json\", \"log_path\": \"worker_analysis_wave3-dir-i-z3-filter_20260520T090105\", \"completed_at\": \"2026-05-20T09:24:00.455Z\"}, \"exp-wave3-dir-j-bootstrap\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:23:14.566Z\", \"updated_at\": \"2026-05-20T09:24:01.932Z\", \"hypothesis\": \"Bootstrapped Gold Approximation: Iterative conditional FOL extraction (using current best answer as condition) with Z3 consistency checks will progressively refine answers across rounds, converging to higher accuracy than single-pass SC.\", \"spec\": {\"command\": \"python direction_j_bootstrap.py\", \"server\": \"westd-16639\", \"data_path\": \"FOLIO-204 + exp-033 traces\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_baseline\": 54.41, \"r1_accuracy\": 56.86, \"r1_delta_pp\": 2.45, \"r1_flips\": 32, \"r1_improved\": 15, \"r1_degraded\": 10, \"r2_accuracy\": 54.41, \"r3_accuracy\": 54.9, \"r4_accuracy\": 54.41, \"r5_accuracy\": 52.45, \"convergence\": \"oscillating, no convergence\"}, \"checkpoint_path\": \"westd-16639:/root/symb_invariant_consensus/results/direction_j_bootstrap/\", \"log_path\": \"worker_experiment_wave3-dir-j-bootstrap_20260520T090123\", \"completed_at\": \"2026-05-20T09:24:01.932Z\"}, \"exp-cross-model-phase2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:20:34.520Z\", \"updated_at\": \"2026-05-20T09:21:07.052Z\", \"hypothesis\": \"Cross-model SICA: Aggregating traces from 3 model families (Mistral+LLaMA+Qwen, K=12 total) via SICA MAX-SAT will outperform cross-model SC by leveraging constraint diversity across architectures.\", \"spec\": {\"command\": \"python cross_model_sica.py\", \"server\": \"westd-25068\", \"data_path\": \"Mistral+LLaMA+Qwen traces FOLIO-204\", \"data_count\": 204, \"model_name\": \"multi-model (Mistral-7B + LLaMA-3.1-8B + Qwen2.5-7B)\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"cross_sc_accuracy\": 74.51, \"cross_sica_accuracy\": 74.02, \"delta_pp\": -0.49, \"mcnemar_p\": 1, \"config\": \"Mistral-7B(4) + LLaMA-8B(4) + Qwen-7B(4), K=12\"}, \"checkpoint_path\": \"westd-25068:/root/symb_invariant_consensus/cross_model_experiment/cross_model_results.json\", \"log_path\": \"worker_analysis_cegis-full-results-and-phase2-check_20260520T085652\", \"completed_at\": \"2026-05-20T09:21:07.052Z\"}, \"exp-direction-d-cegis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:53:01.301Z\", \"updated_at\": \"2026-05-20T09:20:32.244Z\", \"hypothesis\": \"CEGIS: Iterative counterexample-guided constraint refinement will improve SICA by using Z3 counterexamples to strengthen constraints across multiple rounds, breaking the single-pass extraction bottleneck.\", \"spec\": {\"command\": \"python direction_d_cegis.py\", \"server\": \"westd-16639\", \"data_path\": \"FOLIO-204\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_baseline\": 54.41, \"r1_accuracy\": 57.84, \"r1_delta_pp\": 3.43, \"r2_accuracy\": 57.35, \"r2_delta_pp\": 2.94, \"r3_accuracy\": 57.84, \"r3_delta_pp\": 3.43, \"r1_unsat_traces\": 127, \"r2_unsat_traces\": 48, \"r3_unsat_traces\": 25, \"wall_time_min\": 51, \"extraction_calls\": 2448, \"refinement_calls\": 175}, \"checkpoint_path\": \"westd-16639:/root/symb_invariant_consensus/results/direction_d_cegis/\", \"log_path\": \"worker_experiment_direction-d-cegis_20260520T074247\", \"completed_at\": \"2026-05-20T08:55:22.422Z\"}, \"exp-confirmation-bias\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:53:05.574Z\", \"updated_at\": \"2026-05-20T08:55:26.899Z\", \"hypothesis\": \"Confirmation Bias quantification: Self-extracted constraints systematically point toward the majority answer even when it is wrong, creating a bias ratio significantly above 1.0 that explains SICA's failure mode.\", \"spec\": {\"command\": \"python confirmation_bias_analysis.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 SICA results\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"bias_ratio\": 4.97, \"wrong_constraints_when_sica_errs\": 0.833, \"sica_errors_follow_sc\": 0.94}, \"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"worker_analysis_prove-cegis-check-and-confirmation-bias_20260520T082713\", \"completed_at\": \"2026-05-20T08:55:26.899Z\"}, \"exp-cross-model-phase1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:53:03.574Z\", \"updated_at\": \"2026-05-20T08:55:24.052Z\", \"hypothesis\": \"Cross-model aggregation: Mixing traces from different model families (Mistral/LLaMA/Qwen) will reduce inter-trace κ below the same-model ceiling of 0.41, increasing effective sample size.\", \"spec\": {\"command\": \"python cross_model_kappa.py\", \"server\": \"westd-25068\", \"data_path\": \"Mistral+LLaMA+Qwen traces FOLIO-204\", \"data_count\": 204, \"model_name\": \"multi-model\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"kappa_cross\": 0.422, \"kappa_within\": 0.532, \"eff_k_cross\": 2.11, \"eff_k_within\": 1.52, \"accuracy_gain\": 0}, \"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"worker_analysis_cross-model-kappa-phase1\", \"completed_at\": \"2026-05-20T08:55:24.052Z\"}, \"exp-direction-e-abstention\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:52:59.761Z\", \"updated_at\": \"2026-05-20T08:55:21.063Z\", \"hypothesis\": \"Selective Abstention: Per-question answer entropy can serve as a reliable uncertainty signal; abstaining on high-entropy questions will improve accuracy on the remaining covered set.\", \"spec\": {\"command\": \"python direction_e_abstention.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 traces (Mistral-7B FOLIO-204)\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"auroc\": 0.673, \"coverage_80pct_delta_pp\": 4.4, \"coverage_60pct_delta_pp\": 8.8}, \"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"worker_analysis_direction-e-selective-abstention_20260520T074201\", \"completed_at\": \"2026-05-20T08:55:21.063Z\"}, \"exp-wild6-kappa-aware-sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:52:57.421Z\", \"updated_at\": \"2026-05-20T08:55:19.533Z\", \"hypothesis\": \"κ-aware SC: Weighting traces by per-question agreement level (inverse κ) in majority voting will improve SC by giving more weight to diverse-opinion questions where voting has more signal.\", \"spec\": {\"command\": \"python wild6_kappa_aware_sc.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 + cross-model traces\", \"data_count\": 204, \"model_name\": \"multi-model\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"conditions_tested\": 11, \"delta_pp_all\": 0, \"finding\": \"accuracy monotonically increases with agreement, SC already optimal\"}, \"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"worker_analysis_wild6-kappa-aware-sc_20260520T072246\", \"completed_at\": \"2026-05-20T08:55:19.533Z\"}, \"exp-wild1-max-unsat\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:52:55.446Z\", \"updated_at\": \"2026-05-20T08:55:17.946Z\", \"hypothesis\": \"MAX-UNSAT: Penalizing constraints in the unsatisfiable set (MIN-UNSAT variant) will improve SICA by actively downweighting contradictory constraints rather than only rewarding satisfiable ones.\", \"spec\": {\"command\": \"python wild1_max_unsat.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 traces (Mistral-7B FOLIO-204)\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"min_unsat_delta_pp\": -6.5, \"mean_excluded_constraints\": 1.3}, \"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"worker_analysis_wild1-max-unsat_20260520T072215\", \"completed_at\": \"2026-05-20T08:55:17.946Z\"}, \"exp-wild4-process-kappa\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:52:53.205Z\", \"updated_at\": \"2026-05-20T08:55:16.383Z\", \"hypothesis\": \"Process-κ: CoT reasoning process similarity (cosine) correlates with answer agreement, and measuring process-level κ reveals whether traces that agree on answers actually use similar reasoning paths.\", \"spec\": {\"command\": \"python analysis_process_kappa.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 traces (Mistral-7B FOLIO-204)\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"answer_kappa\": 0.4093, \"process_cosine_mean\": 0.6902, \"pearson_r\": -0.064, \"pearson_p\": 0.36, \"same_answer_diff_process_pct\": 9.3}, \"checkpoint_path\": \"westd-25068:/root/symb_invariant_consensus/results/wild4_process_kappa/results.json\", \"log_path\": \"worker_analysis_wild4-process-kappa_20260520T080636\", \"completed_at\": \"2026-05-20T08:55:16.383Z\"}, \"exp-direction-a-prove\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:52:50.909Z\", \"updated_at\": \"2026-05-20T08:55:14.926Z\", \"hypothesis\": \"PROVE: LLM-generated verification code (verify() functions) can serve as external verifiers to rerank SC candidates, bypassing the self-extraction bottleneck.\", \"spec\": {\"command\": \"python direction_a_prove.py\", \"server\": \"westd-25068\", \"data_path\": \"FOLIO-204\", \"data_count\": 204, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"code_gen_rate\": 0.152, \"conclusive_rate\": 0.078, \"conclusive_accuracy\": 0.5, \"prove_fallback_accuracy\": 0.716, \"sc_baseline\": 0.735, \"delta_pp\": -1.9}, \"checkpoint_path\": \"westd-25068:/root/symb_invariant_consensus/results/direction_a_prove/results.json\", \"log_path\": \"worker_experiment_direction-a-prove_20260520T074330\", \"completed_at\": \"2026-05-20T08:55:14.926Z\"}, \"exp-direction-b-deepconf\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:52:49.310Z\", \"updated_at\": \"2026-05-20T08:55:13.277Z\", \"hypothesis\": \"DeepConf: Low-confidence traces (by logprob) produce low-quality constraints; filtering them before SICA will improve accuracy by removing noise from the constraint pool.\", \"spec\": {\"command\": \"python direction_b_deepconf.py\", \"server\": \"westd-25068\", \"data_path\": \"exp-033 traces (Mistral-7B FOLIO-204)\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"conclusion\": \"negative\", \"metrics\": {\"filtered_sc_75pct\": 52.9, \"filtered_sica_75pct\": 54.4, \"filtered_sc_50pct\": 52.9, \"logprob_correct\": -0.135, \"logprob_incorrect\": -0.141, \"delta_pp\": 0}, \"checkpoint_path\": \"N/A (analysis experiment)\", \"log_path\": \"worker_experiment_direction-b-deepconf_20260520T074306\", \"completed_at\": \"2026-05-20T08:55:13.277Z\"}, \"exp-wild3-perturbation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:47:10.815Z\", \"updated_at\": \"2026-05-20T08:48:02.574Z\", \"hypothesis\": \"Problem perturbation (variable renaming, premise reordering) will reduce inter-trace kappa by producing different reasoning paths for semantically equivalent problems, testing whether correlation comes from surface form vs model bias.\", \"spec\": {\"command\": \"python analysis_problem_perturbation.py\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 30, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"results/wild3_perturbation/results.json\", \"log_path\": \"results/wild3_perturbation/\"}, \"conclusion\": \"negative\", \"metrics\": {\"original_k4_kappa\": 0.59, \"perturbed_k4_kappa\": 0.696, \"mixed_k8_kappa\": 0.627, \"original_sc_acc\": 80, \"perturbed_sc_acc\": 76.7, \"mixed_sc_acc\": 80}, \"completed_at\": \"2026-05-20T08:48:02.574Z\"}, \"exp-wild2-ascii\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:47:08.985Z\", \"updated_at\": \"2026-05-20T08:48:01.074Z\", \"hypothesis\": \"ASCII padding in FOLIO prompts will reduce inter-trace Fleiss kappa by disrupting shared surface-level patterns, testing whether trace correlation comes from prompt content vs model architecture bias.\", \"spec\": {\"command\": \"python analysis_ascii_perturbation.py\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_path\": \"results/wild2_ascii_perturbation/results.json\", \"log_path\": \"results/wild2_ascii_perturbation/\"}, \"conclusion\": \"negative\", \"metrics\": {\"group_a_standard_kappa\": 0.3906, \"group_b_fixed_padding_kappa\": 0.4006, \"group_c_variable_padding_kappa\": 0.3638, \"group_a_sc_acc\": 53.92, \"group_b_sc_acc\": 57.84, \"group_c_sc_acc\": 53.92}, \"completed_at\": \"2026-05-20T08:48:01.074Z\"}, \"exp-084-debate-mistral-logiqa-seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T22:33:19.983Z\", \"updated_at\": \"2026-05-20T02:47:44.350Z\", \"hypothesis\": \"Debate × Mistral-7B × LogiQA-200 seed=123 replication. exp-078 (seed=42) Δ=-23.0pp (catastrophic negative). Multi-seed 确认 Debate 在 LogiQA 上的大幅 negative 结果是否跨 seed 稳定。\", \"parent\": \"exp-078-debate-mistral-logiqa200\", \"reproduce\": {\"finished_at\": \"2026-05-19T22:47:45.234Z\"}, \"completed_at\": \"2026-05-20T02:47:44.350Z\", \"extra\": {\"note\": \"First deployment CRON false-positive (PID 295377). Second deployment completed 200/200 successfully.\"}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_debate.py --mode vllm --dataset logiqa --k 12 --n-debates 4 --temperature 0.7 --seed 123 --api-base http://localhost:8001/v1 --model auto --data data/logiqa_200.json --output results/exp084_debate_mistral_logiqa_seed123/results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (inference-only, no fine-tuning)\", \"eval_data\": \"data/logiqa_200.json (200 problems, 4-choice multichoice)\"}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 200, \"debate_accuracy\": 0.29, \"sc_accuracy\": 0.505, \"delta\": -0.215, \"fallbacks\": 14, \"total_constraints\": 3220, \"wall_time_min\": 226.3}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp084_debate_mistral_logiqa_seed123/results.json\", \"log_path\": \"/root/runs/symb_invariant_consensus/exp-084-debate-mistral-logiqa-seed123.log\"}, \"exp-082-contrastive-mistral-folio-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:27:49.643Z\", \"updated_at\": \"2026-05-20T01:00:18.542Z\", \"spec\": {\"command\": \"python -u run_contrastive.py --mode vllm --k 12 --k-contrast 3 --temperature 0.7 --seed 123 --api-base http://localhost:8021/v1 --model auto --data data/folio_full.json --output results/exp082_contrastive_mistral_folio_seed123/results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:1\"], \"pid\": \"211081\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-082-contrastive-mistral-folio-seed123.log\", \"submitted_at\": \"2026-05-19T21:27:49.358Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (base, no fine-tuning)\", \"eval_data\": \"folio_full.json (204 problems)\", \"wall_clock_seconds\": 12749.2, \"gpu_hours\": 3.54}, \"hypothesis\": \"Contrastive × Mistral-7B × FOLIO-204 seed=123 replication: verifying that the contrastive constraint generation pipeline produces consistent accuracy improvements over SC baseline when controlling for random seed, expecting accuracy within ±2pp of seed=42 run (exp-075b)\", \"parent\": \"exp-075b-contrastive-mistral-folio\", \"reproduce\": {\"finished_at\": \"2026-05-20T00:56:03.922Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:56:11.027179+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.549, \"contrastive_accuracy\": 0.4951, \"delta\": -0.0539, \"n_samples\": 204, \"wall_time_min\": 206.3, \"degenerate_count\": 35, \"pro_constraints\": 1036, \"con_constraints\": 920}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp082_contrastive_mistral_folio_seed123/results.json\", \"completed_at\": \"2026-05-20T01:00:18.542Z\"}, \"exp-081-debate-mistral-folio-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:27:47.040Z\", \"updated_at\": \"2026-05-20T00:31:10.579Z\", \"spec\": {\"command\": \"python -u run_debate.py --mode vllm --k 12 --n-debates 4 --temperature 0.7 --seed 123 --api-base http://localhost:8020/v1 --model auto --data data/folio_full.json --output results/exp081_debate_mistral_folio_seed123/results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:0\"], \"pid\": \"211057\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-081-debate-mistral-folio-seed123.log\", \"submitted_at\": \"2026-05-19T21:27:46.742Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (base, no fine-tuning)\", \"eval_data\": \"folio_full.json (204 problems)\", \"wall_clock_seconds\": 11003.8, \"gpu_hours\": 3.06}, \"hypothesis\": \"Debate × Mistral-7B × FOLIO-204 seed=123 replication: verifying that the debate-augmented constraint extraction pipeline produces consistent accuracy improvements over SC baseline when controlling for random seed, expecting accuracy within ±2pp of seed=42 run (exp-076)\", \"parent\": \"exp-076-debate-mistral-folio\", \"reproduce\": {\"finished_at\": \"2026-05-20T00:26:57.955Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:27:01.815562+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.5588, \"debate_accuracy\": 0.4069, \"delta\": -0.152, \"n_samples\": 204, \"wall_time_min\": 177.6, \"fallbacks\": 18, \"both_correct\": 56, \"debate_improved\": 27, \"debate_degraded\": 58, \"both_wrong\": 63}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp081_debate_mistral_folio_seed123/results.json\", \"completed_at\": \"2026-05-20T00:31:10.579Z\"}, \"exp-085-contrastive-mistral-logiqa-seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T22:37:05.631Z\", \"updated_at\": \"2026-05-20T00:21:11.042Z\", \"hypothesis\": \"Contrastive × Mistral-7B × LogiQA-200 seed=123 multi-seed replication。exp-080 (seed=42) Δ=-4.5pp (negative)。跨 seed 确认 Contrastive 在 LogiQA 上的 negative 结果稳定性，排除单 seed 偶然。\", \"parent\": \"exp-080-contrastive-mistral-logiqa200\", \"reproduce\": {\"finished_at\": \"2026-05-20T00:20:02.889Z\"}, \"completed_at\": \"2026-05-20T00:20:02.889Z\", \"extra\": {\"note\": \"First deployment CRON false-positive. Second deployment completed 200/200 successfully.\"}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_contrastive.py --mode vllm --dataset logiqa --k 12 --k-contrast 3 --temperature 0.7 --seed 123 --api-base http://localhost:8002/v1 --model auto --data data/logiqa_200.json --output results/exp085_contrastive_mistral_logiqa_seed123/results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (inference-only, no fine-tuning)\", \"eval_data\": \"data/logiqa_200.json (200 problems, 4-choice multichoice)\"}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 200, \"contrastive_accuracy\": 0.535, \"sc_accuracy\": 0.56, \"delta\": -0.025, \"delta_pp\": -2.5, \"contrastive_correct\": 107, \"sc_correct\": 112, \"k\": 12, \"k_contrast\": 3, \"temperature\": 0.7, \"seed\": 123, \"degenerate_count\": 51, \"total_pro_constraints\": 736, \"total_con_constraints\": 1059, \"wall_time_min\": 100.9}, \"log_path\": \"/root/runs/symb_invariant_consensus/exp-085-contrastive-mistral-logiqa-seed123.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp085_contrastive_mistral_logiqa_seed123/results.json\"}, \"exp-075b-contrastive-mistral-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:31:03.796Z\", \"updated_at\": \"2026-05-19T23:09:01.115Z\", \"hypothesis\": \"Contrastive × Mistral-7B × FOLIO-204 重跑（修复 normalization bug 后）。对每个候选答案生成 pro/con FOL 约束，用 normalized contrastive 评分代替同源约束。exp-075 因 session crash + normalization bug 失败。如果 normalized contrastive 约束提供独立于 traces 的判别信号，delta(Contrastive vs SC) > delta(SICA vs SC)。\", \"parent\": \"exp-075-contrastive-mistral-folio\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_contrastive.py --mode vllm --k 12 --k-contrast 3 --temperature 0.7 --seed 42 --api-base http://localhost:8002/v1 --model auto --data data/folio_full.json --output results/exp075b_contrastive_mistral_folio/results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3\", \"eval_data\": \"data/folio_full.json\", \"checkpoint_path\": \"results/exp075b_contrastive_mistral_folio/results.json\", \"log_path\": \"results/exp075b_contrastive_mistral_folio/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.5686, \"contrastive_accuracy\": 0.4755, \"delta\": -0.0931, \"n_samples\": 204, \"wall_time_min\": 193.6, \"degenerate_count\": 41}, \"completed_at\": \"2026-05-19T21:10:44.839Z\"}, \"exp-080-contrastive-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:14:59.602Z\", \"updated_at\": \"2026-05-19T22:47:45.758Z\", \"hypothesis\": \"Contrastive constraint generation with MAX-SAT consensus (SICA) transfers from FOLIO to LogiQA, improving accuracy over self-consistency baseline on 200 LogiQA problems with Mistral-7B (seed=42).\", \"parent\": \"exp-075b-contrastive-mistral-folio\", \"spec\": {\"command\": \"python -u run_contrastive.py --mode vllm --k 12 --k-contrast 3 --temperature 0.7 --seed 42 --dataset logiqa --api-base http://localhost:8000/v1 --model auto --data data/logiqa_200.json --output results/exp080_contrastive_mistral_logiqa200/results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"pid\": 279841, \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_path\": \"results/exp080_contrastive_mistral_logiqa200/results.json\", \"log_path\": \"results/exp080_contrastive_mistral_logiqa200/train.log\", \"checkpoint_source\": \"vllm-inference-only\", \"eval_data\": \"data/logiqa_200.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T20:40:16.674Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T20:40:18.160Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T20:40:21.407849+00:00\"}]}, \"metrics\": {\"n\": 200, \"contrastive_accuracy\": 0.455, \"sc_accuracy\": 0.5, \"delta\": -0.045, \"k\": 12, \"k_contrast\": 3, \"temperature\": 0.7, \"seed\": 42, \"total_wall_time_s\": 6645.9, \"total_pro_constraints\": 762, \"total_con_constraints\": 1192, \"degenerate_count\": 42}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp080_contrastive_mistral_logiqa200/results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp080_contrastive_mistral_logiqa200/results.json\"}, \"exp-078-debate-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:51:21.070Z\", \"updated_at\": \"2026-05-19T22:29:09.471Z\", \"hypothesis\": \"Debate-augmented extraction with MAX-SAT consensus (SICA) transfers cross-dataset from FOLIO (3-class) to LogiQA (4-choice multichoice), maintaining accuracy gains over self-consistency baseline on 200 LogiQA problems with Mistral-7B.\", \"parent\": \"exp-076-debate-mistral-folio\", \"spec\": {\"command\": \"python -u run_debate.py --mode vllm --dataset logiqa --k 12 --n-debates 4 --temperature 0.7 --seed 42 --api-base http://localhost:8013/v1 --model auto --data data/logiqa_200.json --output results/exp078_debate_mistral_logiqa200/results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": \"cuda:3\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"pid\": 194538, \"log_path\": \"/tmp/exp078_debate_logiqa.log\", \"checkpoint_path\": \"results/exp078_debate_mistral_logiqa200/results.json\", \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (inference-only, no fine-tuning)\", \"eval_data\": \"logiqa_200.json (200 problems, 4-choice multichoice)\", \"vllm_port\": 8013, \"tmux_session\": \"vllm_logiqa\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.5, \"debate_accuracy\": 0.27, \"delta\": -0.23, \"n_samples\": 200, \"wall_time_min\": 211.5, \"fallbacks\": 16}, \"completed_at\": \"2026-05-19T22:29:09.471Z\"}, \"exp-078\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T22:27:35.893Z\", \"updated_at\": \"2026-05-19T22:28:15.797Z\", \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.5, \"debate_accuracy\": 0.27, \"delta\": -0.23, \"n_samples\": 200, \"fallbacks\": 16, \"wall_time_min\": 211.5}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp078_debate_mistral_logiqa200/results.json\", \"log_path\": \"/tmp/exp078_debate_logiqa.log\", \"spec\": {\"command\": \"python run_debate.py --dataset logiqa --n 200\", \"server\": \"westd-16639\", \"data_path\": \"logiqa\", \"data_count\": 200, \"model_name\": \"mistral-7b\", \"seed\": 42}, \"hypothesis\": \"Multi-agent debate among Mistral-7B instances on LogiQA improves accuracy over self-consistency because inter-agent argumentation corrects reasoning errors that independent sampling cannot, yielding a positive delta on 200 problems.\", \"completed_at\": \"2026-05-19T22:28:15.797Z\"}, \"exp-083-icg-mistral-logiqa-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:11:59.619Z\", \"updated_at\": \"2026-05-19T22:22:34.341Z\", \"hypothesis\": \"ICG × Mistral-7B × LogiQA-200 seed=123 multi-seed replication。exp-079 (seed=42) Δ=-0.5pp (negative)。跨数据集 multi-seed 确认 ICG 方法在 LogiQA 上的 negative 结果稳定性。\", \"parent\": \"exp-079-icg-mistral-logiqa200\", \"spec\": {\"command\": \"python -u run_icg.py --mode vllm --k 12 --k-icg 10 --temperature 0.7 --seed 123 --api-base http://localhost:8001/v1 --model auto --data data/logiqa_200.json --output results/exp083_icg_mistral_logiqa_seed123/results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:1\"], \"pid\": \"287652\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-083-icg-mistral-logiqa-seed123.log\", \"submitted_at\": \"2026-05-19T21:15:26.491Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (base, no fine-tuning)\", \"eval_data\": \"data/logiqa_200.json\", \"wall_clock_seconds\": 4021.8, \"gpu_hours\": 1.12}, \"reproduce\": {\"finished_at\": \"2026-05-19T22:18:00.230Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T22:18:04.156058+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp083_icg_mistral_logiqa_seed123/results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-083-icg-mistral-logiqa-seed123.log\", \"completed_at\": \"2026-05-19T22:22:28.330Z\", \"metrics\": {\"n\": 200, \"sc_accuracy\": 0.365, \"icg_accuracy\": 0.33, \"delta_pp\": -3.5, \"sc_correct\": 73, \"icg_correct\": 66, \"both_correct\": 62, \"sc_only\": 11, \"icg_only\": 4, \"neither\": 123, \"mean_constraints_generated\": 31.4, \"mean_constraints_unique\": 27.9, \"mean_maxsat_satisfied\": 27.7, \"mean_maxsat_excluded\": 0.2, \"wall_time_s\": 3653.7, \"mean_wall_time_s\": 18.3}}, \"exp-074d-icg-mistral-folio-seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:43:16.073Z\", \"updated_at\": \"2026-05-19T22:04:19.258Z\", \"hypothesis\": \"ICG × Mistral-7B × FOLIO-204 seed=456 第三组 seed replication。exp-074 (seed=42) Δ=-2.0pp, exp-074c (seed=123) 运行中。3-seed 数据确认 ICG 方法的 negative 结果跨 seed 稳定性，堵住 reviewer 单 seed 质疑。ICG 是三方法中 Δ 最接近零的，3-seed 数据最有论文价值。\", \"parent\": \"exp-074-icg-mistral-folio\", \"spec\": {\"command\": \"python -u run_icg.py --mode vllm --k 12 --k-icg 10 --temperature 0.7 --seed 456 --api-base http://localhost:8003/v1 --model auto --data data/folio_full.json --output results/exp074d_icg_mistral_folio_seed456/results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"283283\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-074d-icg-mistral-folio-seed456.log\", \"submitted_at\": \"2026-05-19T20:44:18.642Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B\", \"seed\": 456, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp074d_icg_mistral_folio_seed456/\", \"checkpoint_source\": \"exp-074-icg-mistral-folio\", \"eval_data\": \"data/folio_full.json\", \"wall_clock_seconds\": 4800.6, \"gpu_hours\": 1.33}, \"reproduce\": {\"finished_at\": \"2026-05-19T21:43:02.856Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T21:43:04.997464+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.5588, \"icg_accuracy\": 0.549, \"delta\": -0.0098, \"n_samples\": 204, \"wall_time_min\": 57.3, \"three_seed_mean_sc\": 0.5572, \"three_seed_mean_icg\": 0.5523, \"three_seed_mean_delta\": -0.0049, \"three_seed_std_delta\": 0.0177, \"three_seed_details\": {\"seed_42\": {\"sc\": 0.5392, \"icg\": 0.5196, \"delta\": -0.0196}, \"seed_123\": {\"sc\": 0.5735, \"icg\": 0.5882, \"delta\": 0.0147}, \"seed_456\": {\"sc\": 0.5588, \"icg\": 0.549, \"delta\": -0.0098}}}, \"completed_at\": \"2026-05-19T22:04:19.258Z\"}, \"exp-077-kappa-generalization\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:30:19.744Z\", \"updated_at\": \"2026-05-19T21:41:15.597Z\", \"hypothesis\": \"High Fleiss kappa (low independence) is a general property of same-model aggregation, not specific to SC+SICA. LLM-Debate and Diverse-Prompt aggregation on Mistral-7B will also exhibit high kappa and low Effective K, confirming the independence bottleneck is fundamental to single-model ensembles regardless of aggregation method.\", \"spec\": {\"command\": \"python -u run_kappa_generalization.py --mode vllm --api-base http://localhost:8012/v1 --model auto --data data/folio_full.json --sc-traces-dir results/exp033_mistral_7b_folio204 --seed 42 --output results/exp077_kappa_generalization/results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_path\": \"results/exp077_kappa_generalization/results.json\", \"log_path\": \"results/exp077_kappa_generalization/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_kappa\": 0.4384, \"sc_eff_k\": 2.02, \"sc_nominal_k\": 10, \"debate_kappa\": 0.1549, \"debate_eff_k\": 4.44, \"debate_nominal_k\": 12, \"diverse_prompt_kappa\": 0.403, \"diverse_prompt_eff_k\": 2.21, \"diverse_prompt_nominal_k\": 12, \"n_samples\": 204}, \"completed_at\": \"2026-05-19T21:41:15.597Z\"}, \"exp-077\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:36:46.336Z\", \"updated_at\": \"2026-05-19T21:37:22.166Z\", \"metrics\": {\"sc_kappa\": 0.4384, \"sc_eff_k\": 2.02, \"debate_kappa\": 0.1549, \"debate_eff_k\": 4.44, \"diverse_prompt_kappa\": 0.403, \"diverse_prompt_eff_k\": 2.21, \"n_questions\": 204, \"all_kappa_gt_04\": false, \"wall_time_min\": 184.9}, \"checkpoint_path\": \"results/exp077_kappa_generalization/results.json\", \"log_path\": \"results/exp077_kappa_generalization/exp077.log\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python run_kappa_generalization.py\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"hypothesis\": \"All three LLM aggregation methods (Self-Consistency, LLM-Debate, Diverse-Prompt) suffer from the same independence bottleneck (Fleiss' κ > 0.4), because the shared model backbone forces correlated reasoning traces regardless of the aggregation strategy used.\", \"completed_at\": \"2026-05-19T21:37:22.166Z\"}, \"exp-075b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:06:51.393Z\", \"updated_at\": \"2026-05-19T21:07:31.931Z\", \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.5686, \"contrastive_accuracy\": 0.4755, \"delta\": -0.0931, \"n_samples\": 204, \"degenerate\": 41, \"wall_time_min\": 193.6}, \"checkpoint_path\": \"results/exp075b_contrastive_mistral_folio/results.json\", \"log_path\": \"results/exp075b_contrastive_mistral_folio/run.log\", \"spec\": {\"command\": \"python run_contrastive.py --dataset folio --model mistral --seed 42\", \"server\": \"westd-25068\", \"data_path\": \"data/folio\", \"data_count\": 204, \"model_name\": \"mistral\", \"seed\": 42}, \"hypothesis\": \"Contrastive pro/con argumentation with normalized scoring improves self-consistency accuracy on FOLIO logical reasoning over standard SC majority voting, by surfacing symbolic invariants through structured debate.\", \"completed_at\": \"2026-05-19T21:07:31.931Z\"}, \"exp-074c-icg-mistral-folio-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:06:50.097Z\", \"updated_at\": \"2026-05-19T21:06:21.214Z\", \"hypothesis\": \"ICG × Mistral-7B × FOLIO-204 seed=123 replication. exp-074 (seed=42) Δ=-2.0pp (negative). Multi-seed replication 确认 ICG 方法的 negative 结果是否跨 seed 稳定。如果 seed=123 也 negative，堵住 reviewer 单 seed 质疑。\", \"parent\": \"exp-074-icg-mistral-folio\", \"spec\": {\"command\": \"python -u run_icg.py --mode vllm --k 12 --k-icg 10 --temperature 0.7 --seed 123 --api-base http://localhost:8001/v1 --model auto --data data/folio_full.json --output results/exp074c_icg_mistral_folio_seed123/results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123, \"checkpoint_source\": \"vllm:/root/autodl-tmp/models/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"data/folio_full.json\"}, \"metrics\": {\"sc_accuracy\": 0.5735, \"icg_accuracy\": 0.5882, \"delta\": 0.0147, \"n_samples\": 204, \"wall_time_min\": 56.5}, \"checkpoint_path\": \"results/exp074c_icg_mistral_folio_seed123/results.json\", \"log_path\": \"results/exp074c_icg_mistral_folio_seed123/run.log\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T21:06:21.214Z\"}, \"exp-076-debate-mistral-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:27:33.106Z\", \"updated_at\": \"2026-05-19T20:40:55.111Z\", \"hypothesis\": \"Debate-Augmented Extraction: 同模型 Proposer/Critic 对抗辩论生成多样化推理路径，从完整辩论记录提取 FOL 约束 + MAX-SAT 评分。在 Mistral-7B FOLIO-204 上测试。Dry-run 3 题 Debate 100% vs SC 67%。如果辩论打破 trace 同源性，delta(Debate vs SC) > delta(SICA vs SC)。parent=exp-033\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_debate.py --mode vllm --k 12 --n-debates 4 --temperature 0.7 --seed 42 --api-base http://localhost:8003/v1 --model auto --data data/folio_full.json --output results/exp076_debate_mistral_folio/results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T17:40:56.663Z\", \"metrics\": {\"sc_accuracy\": 0.5686, \"debate_accuracy\": 0.3824, \"delta\": -0.1863, \"n_samples\": 204, \"wall_time_min\": 186.4, \"fallbacks\": 10, \"total_debate_constraints\": 3677}}, \"exp-079-icg-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T19:06:05.950Z\", \"updated_at\": \"2026-05-19T20:33:29.162Z\", \"hypothesis\": \"ICG × Mistral-7B × LogiQA-200 cross-dataset validation. 验证 ICG 方法在 LogiQA 多选题上是否有效。与 exp-074 (ICG×FOLIO) 和 exp-078 (Debate×LogiQA) 对比，构建方法×数据集交叉矩阵。如果 ICG 在 LogiQA 上也无效，进一步确认 independence bottleneck 的普遍性。\", \"parent\": \"exp-074-icg-mistral-folio\", \"spec\": {\"command\": \"python -u run_icg.py --mode vllm --k 12 --k-icg 10 --temperature 0.7 --seed 42 --api-base http://localhost:8010/v1 --model auto --dataset logiqa --data data/logiqa_200.json --output results/exp079_icg_mistral_logiqa200/results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": \"cuda:0\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"vllm_port\": 8010, \"tmux_session\": \"exp079_run\", \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (pretrained, no fine-tuning)\", \"eval_data\": \"logiqa_200.json\", \"checkpoint_path\": \"results/exp079_icg_mistral_logiqa200/results.json\", \"log_path\": \"results/exp079_icg_mistral_logiqa200/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.475, \"icg_accuracy\": 0.47, \"delta\": -0.005, \"n_samples\": 200, \"wall_time_min\": 54.3}, \"completed_at\": \"2026-05-19T20:33:29.162Z\"}, \"exp-072b-llama8b-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:46:38.067Z\", \"updated_at\": \"2026-05-19T20:02:06.149Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct on LogiQA-200 with canonical SICA code (k=12, seed=42)（重跑）。exp-072 因 session crash 失败。产出 valid comparable SICA scores，replacing exp-069 which used outdated code.\", \"parent\": \"exp-072-llama8b-logiqa200\", \"spec\": {\"command\": \"python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8011/v1 --model auto --data data/logiqa_200.json --output results/exp072b_llama8b_logiqa200/exp072b_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/logiqa_200.json\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp072b_llama8b_logiqa200/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp072b_llama8b_logiqa200/exp072b_run.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T20:02:01.542Z\", \"metrics\": {\"sc_accuracy\": 0.595, \"sica_accuracy\": 0.585, \"delta\": -0.01, \"n_samples\": 200, \"k\": 12, \"wall_time_s\": 7310.5, \"extraction_success\": 2292, \"extraction_fail_json_parse\": 108}}, \"exp-074-icg-mistral-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:06:33.965Z\", \"updated_at\": \"2026-05-19T19:42:58.267Z\", \"hypothesis\": \"ICG (Independent Constraint Generation): 独立于 reasoning traces 生成 FOL 约束，绕过 trace-sourced confirmation bias。直接从问题 premises 提取逻辑约束（不解题），用独立约束 + MAX-SAT 评分候选答案。在 Mistral-7B FOLIO-204 上测试，与标准 SICA (同源约束) 对比。预期：如果独立约束有效，delta(ICG vs SC) > delta(SICA vs SC)。\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_icg.py --mode vllm --k 12 --k-icg 10 --temperature 0.7 --seed 42 --api-base http://localhost:8000/v1 --model auto --data data/folio_full.json --output results/exp074_icg_mistral_folio/results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"checkpoint_path\": \"results/exp074_icg_mistral_folio/results.json\", \"log_path\": \"results/exp074_icg_mistral_folio/\", \"metrics\": {\"sc_accuracy\": 0.5392, \"icg_accuracy\": 0.5196, \"delta\": -0.0196, \"n_samples\": 204, \"k\": 12, \"k_icg\": 10, \"wall_time_s\": 3368}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T19:42:58.267Z\"}, \"exp-073b-qwen7b-logiqa200-seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:46:28.317Z\", \"updated_at\": \"2026-05-19T19:42:57.308Z\", \"hypothesis\": \"Qwen2.5-7B LogiQA seed=456 第三组 seed replication（重跑）。exp-073 因 session crash 失败。exp-070 (seed=42) SC=68.5% Δ=+2.5pp, exp-071 (seed=123) SC=69% Δ=-0.5pp。seed=456 是 Goldilocks tie-breaker。\", \"parent\": \"exp-070-qwen7b-logiqa200\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 456 --api-base http://localhost:8001/v1 --model auto --data data/logiqa_200.json --output results/exp073b_qwen7b_logiqa200_seed456/exp073b_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"Qwen/Qwen2.5-7B-Instruct\", \"eval_data\": \"logiqa_200.json\"}, \"checkpoint_path\": \"results/exp073b_qwen7b_logiqa200_seed456/exp073b_results.json\", \"log_path\": \"results/exp073b_qwen7b_logiqa200_seed456/\", \"metrics\": {\"sc_accuracy\": 0.695, \"sica_accuracy\": 0.715, \"delta\": 0.02, \"n_samples\": 200, \"k\": 12, \"wall_time_s\": 3517.3}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T19:42:57.308Z\"}, \"exp-073-qwen7b-logiqa200-seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:21:57.207Z\", \"updated_at\": \"2026-05-19T18:55:51.568Z\", \"hypothesis\": \"Qwen2.5-7B LogiQA seed=456 第三组 seed replication。exp-070 (seed=42) SC=68.5% Δ=+2.5pp, exp-071 (seed=123) 进行中。seed=456 加固第二个 Goldilocks 数据点。如果 3 seeds 方向一致，累积证据支持 Qwen2.5-7B 在 LogiQA 上处于 Goldilocks regime。\", \"parent\": \"exp-070-qwen7b-logiqa200\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 456 --api-base http://localhost:8000/v1 --model auto --data data/logiqa_200.json --output results/exp073_qwen7b_logiqa200_seed456/exp073_results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 456, \"port\": 8000, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-7B-Instruct\", \"eval_data\": \"data/logiqa_200.json\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T17:40:53.104Z\", \"metrics\": {\"sc_accuracy\": 0.7, \"sica_accuracy\": 0.705, \"delta\": 0.005, \"n_samples\": 200}}, \"exp-072-llama8b-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:21:53.401Z\", \"updated_at\": \"2026-05-19T18:55:50.780Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct on LogiQA-200 with canonical SICA code (k=12, seed=42) will produce valid comparable SICA scores, replacing exp-069 which used outdated code.\", \"parent\": \"\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8011/v1 --model auto --data data/logiqa_200.json --output results/exp072_llama8b_logiqa200/exp072_results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": \"cuda:1\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"port\": 8011}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T17:40:51.311Z\", \"metrics\": {\"sc_accuracy\": 0.62, \"sica_accuracy\": 0.63, \"delta\": 0.01, \"n_samples\": 200}}, \"exp-064-deepseek-r1-qwen3-8b-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:49:07.235Z\", \"updated_at\": \"2026-05-19T18:14:25.428Z\", \"hypothesis\": \"DeepSeek-R1-0528-Qwen3-8B (reasoning distill) 在 FOLIO-204 上 SICA vs SC。测试 reasoning 模型在 8B scale 是否出现 degenerate regime (C₀<5%) 或因 8B 能力较弱落入 error amplification / Goldilocks zone。\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 8192 --folio-data data/folio_full.json --seed 42\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"DeepSeek-R1-0528-Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:0\", \"port\": 8002, \"checkpoint_source\": \"DeepSeek-R1-0528-Qwen3-8B (HuggingFace)\", \"eval_data\": \"data/folio_full.json\", \"notes\": \"Retry of exp-064 (killed on cuda:2). Worker relaunched on cuda:0 with tokenizer fix. Progress ~77/204 as of 12:20 UTC.\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"\", \"notes\": \"code_version=westd-16639-legacy, sica_not_comparable. 旧代码启动，SC 数据可用（不受代码版本影响），SICA/delta 不入 Table 1。Director 指令 2026-05-19T15:25 UTC。\", \"reproduce\": {\"finished_at\": \"2026-05-19T18:11:37.003Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:11:41.587088+00:00\"}]}, \"checkpoint_path\": \"results/exp064_deepseek_r1_qwen3_8b_folio204/results.json\", \"log_path\": \"results/exp064_deepseek_r1_qwen3_8b_folio204/exp064.log\", \"metrics\": {\"sc_accuracy\": 0.8382, \"sica_accuracy\": 0.8382, \"delta\": 0, \"n_samples\": 204, \"extraction_rate\": 0.3818, \"contradiction_rate\": 0.0165, \"wall_time_min\": 355.6}}, \"exp-075-contrastive-mistral-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:27:29.909Z\", \"updated_at\": \"2026-05-19T17:40:54.883Z\", \"hypothesis\": \"Contrastive Constraint Generation: 对每个候选答案生成 pro/con FOL 约束，用对比评分代替同源约束。在 Mistral-7B FOLIO-204 上测试。如果 contrastive 约束提供独立于 traces 的判别信号，delta(Contrastive vs SC) > delta(SICA vs SC)。parent=exp-033\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_contrastive.py --mode vllm --k 12 --k-contrast 3 --temperature 0.7 --seed 42 --api-base http://localhost:8002/v1 --model auto --data data/folio_full.json --output results/exp075_contrastive_mistral_folio/results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T17:40:54.883Z\"}, \"exp-077-generalization-kappa\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:28:58.631Z\", \"updated_at\": \"2026-05-19T17:28:58.631Z\", \"hypothesis\": \"Generalization: independence bottleneck (high κ) applies to Debate and Diverse-Prompt aggregation, not just SC+SICA. 在 Mistral-7B FOLIO-204 上测量 3 种聚合方式的 Fleiss' κ + Eff-K: (a) Standard SC (复用 exp-033 traces), (b) LLM-Debate traces (4组×3轮=12 answer points), (c) Diverse-Prompt traces (4种 prompt×3次=12). 如果三种方式 κ 均 > 0.4，证明 independence bottleneck 是 same-model aggregation 的通病。\"}, \"exp-071-qwen7b-logiqa200-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:36:32.407Z\", \"updated_at\": \"2026-05-19T16:21:44.107Z\", \"hypothesis\": \"exp-070 seed replication: Qwen2.5-7B-Instruct 在 LogiQA-200 上 SICA vs SC, seed=123。exp-070 (seed=42) SC=68.5% Δ=+2.5pp p=0.125, 7 个 discordant pairs 统计功效不足。seed replication 加固 Goldilocks zone claim。如果 seed=123 也给出正向 Δ 且方向一致，则累积证据支持 Qwen2.5-7B 在 LogiQA 上处于 Goldilocks regime。\", \"parent\": \"exp-070-qwen7b-logiqa200\", \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 123 --api-base http://localhost:8001/v1 --model auto --data data/logiqa_200.json --output results/exp071_qwen7b_logiqa200_seed123/exp071_results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:1\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 123, \"port\": 8001, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-7B-Instruct\", \"eval_data\": \"data/logiqa_200.json\", \"tmux_session\": \"exp-071-qwen7b-logiqa200-seed123\", \"vllm_session\": \"exp071_vllm\", \"checkpoint_path\": \"results/exp071_qwen7b_logiqa200_seed123/\", \"log_path\": \"results/exp071_qwen7b_logiqa200_seed123/exp071_results.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.69, \"sica_accuracy\": 0.685, \"delta\": -0.005, \"n_samples\": 200}, \"completed_at\": \"2026-05-19T16:21:44.107Z\"}, \"exp-048-llama8b-pw600\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:30:33.025Z\", \"updated_at\": \"2026-05-19T15:41:14.159Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct 在 ProofWriter-600 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=63.2% delta=-2.45pp (exp-020)。PW 是更结构化的形式推理数据集，测试 SICA 在 PW 上对低能力模型是否有效（补充 regime boundary 跨域证据）。parent=exp-020\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp048_llama8b_pw600/exp048_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:3\", \"tmux_session\": \"exp048_run\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T15:36:25.667Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T15:36:27.043Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T15:36:30.248067+00:00\"}]}, \"notes\": \"code_version=westd-16639-legacy, sica_not_comparable. Reviewer verified: SC=70%, SICA=64.8%, delta=-5.2pp, n=600.\", \"metrics\": {\"sc_accuracy\": 0.7, \"sica_accuracy\": 0.648, \"delta\": -0.052, \"n_samples\": 600}}, \"exp-053-mistral-folio204-seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:36.430Z\", \"updated_at\": \"2026-05-19T15:21:07.978Z\", \"hypothesis\": \"exp-033 replication (seed=456): Mistral-7B FOLIO-204 K=12 T=0.7，第二组独立 replication。与 exp-052 (seed=123) 一起验证 exp-033 结论 robustness。parent=exp-033\", \"conclusion\": \"killed\", \"notes\": \"Stale duplicate. 实际实验已在 exp-053 (短 ID) 下完成 (DONE)。本条目是重复创建的长名称版本，清理。\", \"completed_at\": \"2026-05-19T15:21:07.978Z\"}, \"exp-052-mistral-folio204-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:34.705Z\", \"updated_at\": \"2026-05-19T15:21:07.037Z\", \"hypothesis\": \"exp-033 replication (seed=123): Mistral-7B FOLIO-204 K=12 T=0.7，与 exp-033 (seed=42, delta=+4.90pp, p=0.013) 完全相同配置，仅 seed 不同。验证正向结果是否 seed-robust。parent=exp-033\", \"conclusion\": \"killed\", \"notes\": \"Stale duplicate. 实际实验已在 exp-052 (短 ID) 下完成 (DONE)。本条目是重复创建的长名称版本，清理。\", \"completed_at\": \"2026-05-19T15:21:07.037Z\"}, \"exp-069-llama8b-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:40:15.817Z\", \"updated_at\": \"2026-05-19T15:15:54.692Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)。LogiQA 上 Mistral-7B SC=51% delta=+0.5pp (exp-049b)，Qwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)。测试 LLaMA-8B 在 LogiQA 上的 regime（SC 预计 50-60%，可能在 error amplification zone）。parent=exp-063-llama8b-folio204-16639\", \"parent\": \"exp-063-llama8b-folio204-16639\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8012/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --folio-data data/empty.json --math-data data/empty.json --pw-data data/empty.json --output results/exp069_llama8b_logiqa200/exp069_results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": \"cuda:2\", \"port\": 8012, \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42}, \"notes\": \"code_version=westd-16639-legacy. Reviewer verified: SC=61%, SICA=58.5%, delta=-2.5pp, n=200.\", \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"\", \"reproduce\": {\"finished_at\": \"2026-05-19T14:32:03.443Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:32:09.270208+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.61, \"sica_accuracy\": 0.585, \"delta\": -0.025, \"n_samples\": 200}}, \"exp-065-qwen7b-pw600\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T08:49:16.855Z\", \"updated_at\": \"2026-05-19T15:15:51.839Z\", \"hypothesis\": \"Qwen2.5-7B 在 PW-D5-600 上 SICA vs SC。FOLIO SC=75.98% (confirmation bias)，PW 更难 SC 预计更低，测试不同 regime。parent=exp-061\", \"parent\": \"\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8010/v1 --model auto --folio-data data/empty.json --math-data data/empty.json --pw-data data/proofwriter_full.json --output results/exp065_qwen7b_pw600/exp065_results.json\", \"server\": \"westd-25068\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"port\": 8010, \"tmux_vllm\": \"exp065_vllm\", \"tmux_run\": \"exp065_run\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T14:43:56.344Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T14:43:57.775Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:44:00.708424+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.72, \"sica_accuracy\": 0.68, \"delta\": -0.04, \"n_samples\": 600}}, \"exp-062-gemma27b-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:41:54.628Z\", \"updated_at\": \"2026-05-19T15:15:50.853Z\", \"hypothesis\": \"Gemma-3-27B-IT (Google 架构) FOLIO-204 SICA vs SC。跨模型家族验证 regime-dependent pattern。27B 能力预计在 Qwen2.5-14B (~75% SC) 和 Qwen3-14B (~85% SC) 之间。\", \"spec\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"model_name\": \"gemma-3-27b-it\", \"data_count\": 204, \"seed\": 42, \"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8003/v1 --model auto --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp062_gemma27b_folio204/exp062_results.json --save-intermediates\", \"data_path\": \"data/folio_full.json\", \"tmux_session\": \"exp062_run\", \"vllm_session\": \"exp062_vllm\", \"vllm_max_model_len\": 8192}, \"reproduce\": {\"finished_at\": \"2026-05-19T15:09:43.653Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T15:09:44.959Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T15:09:47.893526+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.809, \"sica_accuracy\": 0.804, \"delta\": -0.005, \"n_samples\": 204}}, \"exp-069-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:50:28.223Z\", \"updated_at\": \"2026-05-19T14:19:37.076Z\", \"hypothesis\": \"Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral 是唯一 Goldilocks 候选 (SC≈55%, Δ=+4.90pp seed=42)。如果 LogiQA SC 也在 55-65% 且 Δ>0，则跨数据集验证 Goldilocks zone 存在。parent=exp-033\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8001/v1 --model auto --data data/logiqa_200.json --output results/exp069_mistral_logiqa200/exp069_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"gpu\": \"cuda:1\", \"port\": 8001, \"tmux_session\": \"exp-069-mistral-logiqa200\", \"vllm_session\": \"exp069_vllm\", \"log_path\": \"/root/symb_invariant_consensus/results/exp069_mistral_logiqa200/exp069_results.json\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp069_mistral_logiqa200/\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:12:53.430Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:12:56.873986+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.495, \"sica_accuracy\": 0.465, \"delta\": -0.03, \"n_samples\": 200}, \"completed_at\": \"2026-05-19T13:56:33.286Z\", \"notes\": \"与 exp-049b 结果不一致调查：5/7 SICA 核心模块代码版本不同（md5 全部不匹配）。关键差异：scorer.py tie-breaking（049b: max() 随机 vs 069: sorted() 字母序）、constraint_extractor/z3_maxsat/pipeline 均有变化。049b 还设了 VLLM_USE_FLASHINFER_SAMPLER=0。prompt 模板相同。两组数据不可直接比较。exp-069 使用 westd-25068 上的最新代码版本。\"}, \"exp-070-qwen7b-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:40:18.453Z\", \"updated_at\": \"2026-05-19T14:18:52.579Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO 上 SC=75.98% (Type A confirmation bias, Δ=+0.49pp)。LogiQA 可能更难，SC 可能降到 55-65% 进入 Goldilocks zone，或保持 >75% 继续 Type A。验证 regime 跨数据集一致性。parent=exp-061\", \"parent\": \"exp-061\", \"spec\": {\"command\": \"python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8002/v1 --model auto --data data/logiqa_200.json --output results/exp070_qwen7b_logiqa200/exp070_results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"pid\": \"213756\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-070-qwen7b-logiqa200.log\", \"submitted_at\": \"2026-05-19T11:56:05.650Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"port\": 8002, \"tmux_session\": \"exp-070-qwen7b-logiqa200\", \"vllm_session\": \"exp070_vllm\", \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-7B-Instruct\", \"eval_data\": \"data/logiqa_200.json\", \"wall_clock_seconds\": 3630.6, \"gpu_hours\": 1.01}, \"reproduce\": {\"finished_at\": \"2026-05-19T12:56:34.965Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T12:56:36.273Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T12:56:40.490804+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.685, \"sica_accuracy\": 0.71, \"delta\": 0.025, \"n_samples\": 200, \"sc_correct\": 137, \"sica_correct\": 142, \"discordant_b\": 1, \"discordant_c\": 6, \"mcnemar_chi2\": 2.2857, \"mcnemar_p\": 0.131, \"mcnemar_p_exact\": 0.125, \"significant_005\": false, \"cohens_kappa\": 0.917, \"kappa_interpretation\": \"almost_perfect\"}, \"notes\": \"Reviewer 独立验证（从 exp070_results.json 确认）：SC=137/200=68.5%, SICA=142/200=71.0%, Δ=+2.5pp。原 diagnostic worker 读取了错误数据源，误报 SC=SICA=79.5%（差距 11pp/22题）。已由 Director 指令修正。\"}, \"exp-068-qwen3-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:13:19.371Z\", \"updated_at\": \"2026-05-19T13:53:10.914Z\", \"hypothesis\": \"Qwen3-14B non-thinking 在 LogiQA-200 上 SICA vs SC。FOLIO SC=84.80%, PW SC=85.0%，LogiQA 预计也在 confirmation bias zone。验证跨数据集 Type A 一致性。parent=exp-040\", \"parent\": \"exp-040\", \"spec\": {\"log_path\": \"/root/symb_invariant_consensus/results/exp068_qwen3_logiqa200/exp068.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp068_qwen3_logiqa200/exp068_results.json\"}, \"notes\": \"Reviewer 独立验证：输出文件完整，200/200 样本已处理。SC=SICA=0.81，null effect。原被 CRON 错误标记为 failed（无 W&B 数据时默认标 failed）。\", \"reproduce\": {\"finished_at\": \"2026-05-19T13:07:59.122Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T13:08:00.470Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:08:03.397783+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.81, \"sica_accuracy\": 0.81, \"delta\": 0, \"n_samples\": 200}}, \"exp-064\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T08:56:53.587Z\", \"updated_at\": \"2026-05-19T12:13:57.742Z\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 8192 --folio-data data/folio_full.json --seed 42\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"DeepSeek-R1-0528-Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:2 (RTX PRO 6000 Blackwell)\", \"port\": 8002, \"notes\": \"Fixed tokenizer: LlamaTokenizerFast->PreTrainedTokenizerFast. VLLM_USE_FLASHINFER_SAMPLER=0 for Blackwell.\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T12:13:57.742Z\"}, \"exp-067-mistral-folio-seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T09:14:16.096Z\", \"updated_at\": \"2026-05-19T12:10:24.878Z\", \"hypothesis\": \"Mistral-7B FOLIO seed=789 第4 seed replication。已有 s42 +3.43pp, s123 +2.94pp, s456 0.00pp。增加统计样本验证 seed variance 和 SC-Δ 相关性。parent=exp-033\", \"parent\": \"exp-033\", \"spec\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"data_count\": 204, \"seed\": 789, \"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 789 --api-base http://localhost:8012/v1 --model auto --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp067_mistral_folio_seed789/exp067_results.json\", \"data_path\": \"data/folio_full.json\", \"checkpoint_source\": \"/root/autodl-tmp/models/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"data/folio_full.json\", \"log_path\": \"results/exp067_mistral_folio_seed789/\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:21:00.412Z\", \"metrics\": {\"sc_accuracy\": 0.5441, \"sica_accuracy\": 0.5392, \"delta_pp\": -0.49, \"n\": 204, \"mcnemar_b\": 6, \"mcnemar_c\": 5, \"mcnemar_p\": 1, \"mcnemar_significant\": false, \"fleiss_kappa_raw\": 0.4124, \"eff_k\": 2.17}}, \"exp-063-llama8b-folio204-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:40:38.262Z\", \"updated_at\": \"2026-05-19T12:02:49.523Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct 在 FOLIO-204 上 SICA vs SC。此前 exp-020 在不同服务器上跑过 (SC=63.2%, delta=-2.45pp)，本实验在 westd-16639 复现并用修正后的 alphabetical tie-breaking SC。parent=exp-020\", \"parent\": \"exp-020\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8004/v1 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp-063-llama8b-folio204-16639/results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/folio_full.json\", \"log_path\": \"results/exp-063-llama8b-folio204-16639/exp063.log\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.6618, \"sica_accuracy\": 0.6176, \"delta_pp\": -4.41, \"n\": 204, \"mcnemar_b\": 16, \"mcnemar_c\": 7, \"mcnemar_p\": 0.0931, \"mcnemar_significant\": false}, \"completed_at\": \"2026-05-19T11:20:59.372Z\"}, \"exp-063-llama8b-folio204\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:34:18.492Z\", \"updated_at\": \"2026-05-19T11:34:19.817Z\", \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.6618, \"sica_accuracy\": 0.6176, \"delta_pp\": -4.41}}, \"exp-061-qwen7b-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:18:30.356Z\", \"updated_at\": \"2026-05-19T11:34:17.303Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 FOLIO-204 上 SICA vs SC。SC 预计 55-65%（介于 Mistral-7B ~55% 和 Qwen2.5-14B ~75% 之间），可能在 Goldilocks zone。\", \"parent\": \"exp-033\", \"spec\": {\"server\": \"westd-25068\", \"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8002/v1 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp061_qwen25_7b_folio204/exp061_results.json --save-intermediates\", \"gpu\": \"cuda:2\", \"model_name\": \"Qwen2.5-7B-Instruct\", \"data_count\": 204, \"seed\": 42, \"data_path\": \"data/folio_full.json\", \"checkpoint_source\": \"pretrained:/root/autodl-tmp/models/Qwen2.5-7B-Instruct\", \"eval_data\": \"data/folio_full.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.7598, \"sica_accuracy\": 0.7647, \"delta_pp\": 0.49}, \"checkpoint_path\": \"results/exp061_qwen25_7b_folio204/exp061_results.json\", \"log_path\": \"results/exp061_qwen25_7b_folio204/\", \"completed_at\": \"2026-05-19T11:18:36.357Z\"}, \"exp-059-cross-qwen3-extractor\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:45:04.278Z\", \"updated_at\": \"2026-05-19T11:34:15.561Z\", \"hypothesis\": \"Qwen3-14B cross-model extraction should produce higher quality FOL constraints than Mistral-7B self-extraction (breaking confirmation bias), leading to higher SICA discriminative rate and accuracy delta over SC baseline.\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python scripts/cross_model_extract.py --traces-dir results/exp033_mistral_7b_folio204/intermediates --output results/exp059_cross_qwen3_extractor/exp059_results.json --qwen3-nothink --temperature 0.3\", \"server\": \"westd-25068\", \"data_path\": \"/root/symb_invariant_consensus/results/exp033_mistral_7b_folio204/intermediates\", \"data_count\": 204, \"model_name\": \"Qwen3-14B (extractor) + Mistral-7B (trace generator)\", \"seed\": \"n/a\", \"checkpoint_source\": \"Qwen/Qwen3-14B from /root/autodl-tmp/models/Qwen3-14B\", \"eval_data\": \"FOLIO-204 validation set (Mistral-7B K=12 traces from exp-033)\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"cross_sica_accuracy\": 0.6029, \"orig_sica_accuracy\": 0.5931, \"sc_accuracy\": 0.5588, \"delta_cross_vs_sc_pp\": 4.41, \"delta_cross_vs_orig_pp\": 0.98}, \"checkpoint_path\": \"results/exp059_cross_qwen3_extractor/exp059_results.json\", \"log_path\": \"results/exp059_cross_qwen3_extractor/\", \"completed_at\": \"2026-05-19T11:18:35.259Z\"}, \"exp-063\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:40:39.276Z\", \"updated_at\": \"2026-05-19T11:20:57.939Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct FOLIO-204 SICA vs SC（Meta 架构覆盖）。exp-020 旧数据 SC=63.2% delta=-2.45pp，本实验用修正 tie-breaking 重跑。parent=exp-020\", \"parent\": \"exp-020\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8004/v1 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp-063-llama8b-folio204-16639/exp063_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Meta-Llama-3.1-8B-Instruct (off-the-shelf)\", \"eval_data\": \"FOLIO-204\", \"log_path\": \"results/exp-063-llama8b-folio204-16639/exp063.log\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.6618, \"sica_accuracy\": 0.6176, \"delta_pp\": -4.41}, \"completed_at\": \"2026-05-19T11:20:57.939Z\"}, \"exp-040-qwen3-pw600-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:31.954Z\", \"updated_at\": \"2026-05-19T11:03:11.142Z\", \"hypothesis\": \"Qwen3-14B non-thinking 在 ProofWriter-600 全量上 SICA vs SC：跨模型代际验证 capability trap 在 PW 数据集上是否持续。与 exp-039 (Qwen2.5-14B PW-600) 对比代际差异。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8001/v1 --model auto --seed 42 --pw-data data/proofwriter_full.json --folio-data data/empty.json --math-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-14B (cached, enable_thinking=false)\", \"eval_data\": \"ProofWriter-600\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp033_qwen3_14b_pw600_nonthinking/results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp033_qwen3_14b_pw600_nonthinking/exp033.log\"}, \"notes\": \"westd-16639 实际目录: exp033_qwen3_14b_pw600_nonthinking, tmux: exp033, port: 8001, GPU 1. 162/600 (27.0%) at 22:28 UTC. Qwen3-14B thinking=false, 推理速度约为 Qwen2.5-14B 的一半。\", \"conclusion\": \"negative\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 0.85, \"sica_accuracy\": 0.8567, \"delta_pp\": 0.67, \"extraction_rate\": 0.997, \"contradiction_rate\": 0.004, \"wall_time_min\": 1032.2, \"failure_type\": \"Type A (confirmation bias)\"}, \"completed_at\": \"2026-05-19T11:01:11.894Z\"}, \"exp-060-cross-qwen25-14b-extractor\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:38:50.075Z\", \"updated_at\": \"2026-05-19T08:33:33.071Z\", \"hypothesis\": \"Qwen2.5-14B 跨模型提取 FOL 约束。与 exp-033 (Mistral self-extraction) 和 exp-059 (Qwen3 cross-extraction) 对比。parent=exp-033\", \"spec\": {\"command\": \"python scripts/cross_model_extract.py --traces-dir results/exp033_mistral_7b_folio204/intermediates --api-base http://localhost:8001/v1 --model auto --temperature 0.3 --output results/exp060_cross_qwen25_14b_extractor/exp060_results.json --resume\", \"server\": \"westd-25068\", \"data_path\": \"results/exp033_mistral_7b_folio204/intermediates\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 0, \"checkpoint_path\": \"results/exp060_cross_qwen25_14b_extractor/exp060_results.json\", \"log_path\": \"results/exp060_cross_qwen25_14b_extractor/exp060.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T08:32:15.336Z\", \"metrics\": {\"n\": 204, \"cross_sica_accuracy\": 0.5833, \"orig_sica_accuracy\": 0.5931, \"sc_accuracy\": 0.5588, \"delta_cross_vs_sc_pp\": 2.45, \"delta_cross_vs_orig_pp\": -0.98, \"divergence_rate\": 0.059, \"wall_time_min\": 106.1}}, \"exp-057-mistral-folio204-t03\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:49:57.330Z\", \"updated_at\": \"2026-05-19T07:37:40.489Z\", \"hypothesis\": \"T=0.3 低温 traces 更确定性更一致，SICA delta < T=0.7 的 +4.90pp。与 exp-054 (T=1.0, +0.49pp) 共同形成 T sensitivity ablation curve。parent=exp-033, D060 analysis paper\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.3 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp057_mistral_folio204_t03/exp057_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"n/a\", \"eval_data\": \"data/folio_full.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T04:20:43.571Z\"}, \"failure_reason\": \"cron auto-resolved as failed (false positive: experiment completed successfully, data n=204 verified)\", \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.5833, \"sica_accuracy\": 0.5686, \"delta_pp\": -1.47, \"mcnemar_p\": 0.5488}, \"completed_at\": \"2026-05-19T04:20:44.783Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T04:20:49.931597+00:00\"}]}}, \"exp-034\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:15:24.666Z\", \"updated_at\": \"2026-05-19T05:50:00.000Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 ProofWriter-600 上 SICA vs SC（westd-25068 重跑）：在 full 600 题上验证 capability trap，复现 sica_expanded_14b 的 PW 子集结果（delta=+0.3pp）。代替原 StrategyQA 实验（exp-034 v1 因 extraction prompt bug + 平台 kill 失败）。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=1 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8001 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp034.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8001/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp034_qwen25_14b_proofwriter/exp034_results.json --save-intermediates 2>&1 | tee results/exp034_qwen25_14b_proofwriter/exp034.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:1\"], \"pid\": \"68543\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-034.log\", \"submitted_at\": \"2026-05-18T17:44:32.378Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12424.8, \"gpu_hours\": 3.45}, \"conclusion\": \"negative\", \"metrics\": {\"n_problems\": 93, \"n_target\": 600, \"completion_pct\": 15.5, \"sica_accuracy\": 77.42, \"sc_accuracy\": 74.19, \"delta_pp\": 3.23, \"sica_correct\": 72, \"sc_correct\": 69, \"mcnemar_discordant_b\": 6, \"mcnemar_discordant_c\": 3, \"mcnemar_p_value\": 0.5078, \"c0_non_unanimous_rate\": 0.581, \"avg_majority_frac\": 0.8324, \"extraction_rate\": 99.19, \"contradiction_rate\": 11.83, \"problems_with_contradictions\": 11, \"avg_unique_constraints\": 35.6, \"total_constraints\": 14437, \"unique_constraints\": 3308, \"dedup_ratio\": 22.9, \"k\": 12, \"level\": \"OWA-D5\", \"gt_distribution\": {\"True\": 32, \"False\": 28, \"Unknown\": 33}, \"wall_time_s\": 6086.4, \"status_note\": \"INCOMPLETE: crashed at 93/600 (python not found after conda env lost)\"}, \"notes\": \"v4 完成。tmux=exp034_run, westd-25068 cuda:1。Qwen2.5-14B on PW-600, delta=+0.50pp (不显著)。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp034_qwen25_14b_proofwriter/exp034_results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-034.log\", \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:28.841Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:32.634997+00:00\"}]}, \"completed_at\": \"2026-05-18T21:11:37.217Z\"}, \"exp-039-14b-pw600-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:31.038Z\", \"updated_at\": \"2026-05-19T04:53:50.957Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 ProofWriter-600 全量上 SICA vs SC（westd-16639 重跑）：验证 capability trap 在 PW 数据集全量规模上是否持续。复现 sica_expanded_14b 的 PW 子集结果（delta=+0.3pp）。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --pw-data data/proofwriter_full.json --folio-data data/empty.json --math-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"ProofWriter-600\"}, \"notes\": \"westd-16639 实际目录: exp032_qwen25_14b_pw600, tmux: exp032, port: 8000, GPU 0. 263/600 (43.8%) at 22:28 UTC.\", \"reproduce\": {\"finished_at\": \"2026-05-19T04:53:49.681Z\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T04:53:50.957Z\", \"metrics\": {\"sica_accuracy\": 71.5, \"sc_accuracy\": 73.5, \"delta_pp\": -2.0, \"n_problems\": 600, \"extraction_rate\": 99.2, \"wall_time_min\": 659.6}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp032_qwen25_14b_pw600/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp032_qwen25_14b_pw600/\"}, \"exp-058-mistral-folio204-t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:10:13.574Z\", \"updated_at\": \"2026-05-19T04:38:50.593Z\", \"hypothesis\": \"T=0.5 delta 介于 T=0.3 和 T=0.7 之间，形成温度-SICA delta 曲线。与 exp-033 (T=0.7, +4.90pp) 和 exp-054 (T=1.0, +0.49pp) 共同构成 4 点 T sensitivity ablation。parent=exp-033, D060 analysis paper\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.5 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp058_mistral_folio204_t05/exp058_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (base, no finetune)\", \"eval_data\": \"FOLIO-204 (data/folio_full.json)\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 57.84, \"sica_accuracy\": 57.35, \"delta_pp\": -0.49, \"mcnemar_p\": 1, \"discordant_b\": 3, \"discordant_c\": 2, \"n_problems\": 204, \"n_completed\": 204, \"extraction_rate\": 97, \"wall_time_min\": 80}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp058_mistral_folio204_t05/exp058_results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp058_mistral_folio204_t05/exp058.log\", \"completed_at\": \"2026-05-19T04:38:50.593Z\"}, \"exp-051-mistral-k-sensitivity\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:32:12.672Z\", \"updated_at\": \"2026-05-19T04:37:35.722Z\", \"hypothesis\": \"Mistral-7B K sensitivity on FOLIO-204: K=[4,8,16,20]（K=12 已有 exp-033 delta=+4.90pp）。验证正向结果对 K 选择是否稳健。Reviewer 必问 ablation。parent=exp-033\", \"spec\": {\"command\": \"bash scripts/run_exp051_k_sensitivity.sh\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 816, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp051_mistral_k_sensitivity/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp051_mistral_k_sensitivity/k20/k20.log\", \"metrics\": {\"K4\": {\"SC\": 54.41, \"SICA\": 52.94, \"delta\": -1.47, \"b\": 7, \"c\": 10, \"McNemar_p\": 0.6291}, \"K8\": {\"SC\": 57.35, \"SICA\": 56.37, \"delta\": -0.98, \"b\": 4, \"c\": 6, \"McNemar_p\": 0.7539}, \"K12_exp033\": {\"SC\": 54.41, \"SICA\": 59.31, \"delta\": 4.9, \"b\": 12, \"c\": 2, \"McNemar_p\": 0.0129}, \"K16\": {\"SC\": 55.88, \"SICA\": 57.35, \"delta\": 1.47, \"b\": 10, \"c\": 7, \"McNemar_p\": 0.6291}, \"K20\": {\"SC\": 57.35, \"SICA\": 59.31, \"delta\": 1.96, \"b\": 5, \"c\": 1, \"McNemar_p\": 0.2188}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T04:37:33.691Z\", \"notes\": \"K sensitivity 完整 5 点数据确认 K=12 是最优点（delta=+4.90pp, p=0.013）。K<12 SICA 不如 SC（K=4: -1.47pp, K=8: -0.98pp），K>12 delta 回落但仍为正（K=16: +1.47pp, K=20: +1.96pp）。整体呈 peaked 曲线（非严格倒 U，K=20 略高于 K=16），但 K=12 peak 显著且两侧衰减明确。McNemar 仅 K=12 显著（p=0.013），其余 K 值均不显著。\"}, \"exp-055-multitemp-mistral-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:17:09.293Z\", \"updated_at\": \"2026-05-19T03:53:56.005Z\", \"hypothesis\": \"Multi-temperature sampling 通过强制 trace diversity 提升 Effective-K，预期 SICA delta > exp-033 的 +4.9pp。混合 T=0.3/0.7/1.2 各 4 traces 比单一 T=0.7 的 12 traces 产生更多独立视角，从而让 MAX-SAT 有更多 discriminative 信号。parent=exp-033, D059\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_multi_temp.py --mode vllm --temperatures 0.3,0.7,1.2 --k-per-temp 4,4,4 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp055_multitemp_mistral_folio/exp055_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (pretrained)\", \"eval_data\": \"data/folio_full.json\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp055_multitemp_mistral_folio/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp055_multitemp_mistral_folio/exp055.log\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 57.84, \"sica_accuracy\": 57.84, \"delta_pp\": 0, \"discordant_b\": 5, \"discordant_c\": 5, \"mcnemar_p\": 1, \"significant\": false, \"agreement_rate\": 0.951, \"wall_time_min\": 83.2, \"temperatures\": \"0.3,0.7,1.2\", \"k_per_temp\": \"4,4,4\"}, \"completed_at\": \"2026-05-19T03:52:57.065Z\"}, \"exp-028b-qwen3-thinking-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:30:30.635Z\", \"updated_at\": \"2026-05-19T03:34:08.736Z\", \"hypothesis\": \"Qwen3-14B thinking mode (enable_thinking=True, 32K context) 在 FOLIO-204 上 SICA vs SC。D028 pilot (35/204, delta=+2.86pp) 被 kill。thinking mode 产生更 diverse+higher-quality reasoning traces，如果同时提升 trace quality 和 diversity，可能打破 14B 级别的 capability trap。parent=exp-028\", \"spec\": {\"command\": \"bash run_exp028b.sh (tmux session: exp028b)\", \"server\": \"westd-25068\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"port\": 8003, \"max_model_len\": 32768, \"max_tokens\": 16384, \"temperature\": 0.7, \"k\": 12, \"mode\": \"thinking\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T03:19:42.424Z\"}, \"failure_reason\": \"cuda:3 回收给 exp-058 T sensitivity ablation（资源冲突，非 OOM）。166/204 已完成，待 exp-058 完成后 resume。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T03:19:44.303Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T03:19:49.420748+00:00\"}]}, \"notes\": \"失败根因：exp-058 部署到 cuda:3+port:8003 覆盖了 exp-028b 的 vLLM（非 OOM）。166/204 已完成，intermediates 完整保存。支持 resume（仅需 38 题 ~90min），但需等 exp-058 完成释放 cuda:3。\"}, \"exp-052\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:20:17.415Z\", \"updated_at\": \"2026-05-19T02:47:07.125Z\", \"hypothesis\": \"Seed replication of exp-033: the +4.90pp improvement on FOLIO-204 with Mistral-7B using symbolic invariant consensus (K=12) is reproducible across different random seeds, confirming the result is not a statistical fluke.\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 123 --math-data data/empty.json --pw-data data/empty.json --strategyqa-data data/empty.json --folio-data data/folio_full.json --output results/exp052_mistral_folio204_seed123/exp052_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123}, \"metrics\": {\"n\": 204, \"sc_accuracy\": 53.9, \"sica_accuracy\": 57.4, \"sc_correct\": 110, \"sica_correct\": 117, \"delta_pp\": 3.43, \"discordant_b\": 8, \"discordant_c\": 1, \"extraction_rate\": 0.971, \"contradiction_rate\": 0.034, \"wall_time_min\": 81.9, \"mcnemar_p\": 0.0391, \"significant\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T01:03:00.000Z\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp052_mistral_folio204_seed123/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp052_mistral_folio204_seed123/exp052.log\", \"notes\": \"Seed=123: SICA=57.35% vs SC=53.92%, delta=+3.43pp, b=8, c=1, p=0.039. High entropy 区域 delta=+7.14pp。2/3 seeds 显著。\", \"parent\": \"exp-033\"}, \"exp-054-mistral-folio204-t10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:17:52.972Z\", \"updated_at\": \"2026-05-19T02:44:50.785Z\", \"hypothesis\": \"T=1.0 增大 trace diversity，Adaptive SICA（high entropy 子集）delta 应 ≥ T=0.7 的 +4.9pp。更高温度 → 更多 high-entropy 问题 → SICA 在更大子集上有效 → overall delta 可能更大。同时测试 exp-033 (+4.9pp at T=0.7) 对温度的敏感性。parent=exp-033\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 1.0 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --folio-data data/folio_full.json --output results/exp054_mistral_folio204_t10/exp054_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (pretrained, no fine-tuning)\", \"eval_data\": \"data/folio_full.json\", \"log_path\": \"results/exp054_mistral_folio204_t10/exp054.log\", \"checkpoint_path\": \"results/exp054_mistral_folio204_t10/exp054_results.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T02:44:47.966Z\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 54.9, \"sica_accuracy\": 55.4, \"delta_pp\": 0.49, \"discordant_b\": 5, \"discordant_c\": 4, \"mcnemar_chi2\": 0.1111, \"mcnemar_p\": 0.7389, \"extraction_rate\": 97.3, \"contradiction_rate\": 3, \"wall_time_min\": 83}}, \"exp-046-mistral-pw600\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:16:46.346Z\", \"updated_at\": \"2026-05-19T01:15:51.422Z\", \"hypothesis\": \"Mistral-7B-Instruct-v0.3 在 ProofWriter-600 上 SICA vs SC：验证 regime boundary 跨域泛化。exp-033 (Mistral FOLIO-204) 显示 +4.90pp (p=0.013)，如果 PW-600 也显示正向 delta，则 regime-dependent capability trap 不是 FOLIO-specific artifact。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-18T20:17:41.279Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp046_mistral_7b_pw600 && CUDA_VISIBLE_DEVICES=2 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8002 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp046.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp046_mistral_7b_pw600/exp046_results.json --save-intermediates 2>&1 | tee results/exp046_mistral_7b_pw600/exp046.log\\\"\", \"finished_at\": \"2026-05-19T01:11:58.516Z\", \"training_hours\": 4.9}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp046_mistral_7b_pw600 && CUDA_VISIBLE_DEVICES=2 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8002 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp046.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp046_mistral_7b_pw600/exp046_results.json --save-intermediates 2>&1 | tee results/exp046_mistral_7b_pw600/exp046.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"95707\", \"log_path\": \"/root/symb_invariant_consensus/results/exp046_mistral_7b_pw600/exp046.log\", \"submitted_at\": \"2026-05-18T20:17:43.014Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp046_mistral_7b_pw600/\", \"wall_clock_seconds\": 17888.4, \"gpu_hours\": 4.97}, \"pid\": \"95707\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-046-mistral-pw600.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T01:12:02.839310+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 39.33, \"sica_accuracy\": 36.5, \"delta_pp\": -2.83, \"sc_wins\": 30, \"sica_wins\": 13, \"mcnemar_p\": 0.0095, \"significant\": true, \"dataset\": \"ProofWriter-D5-600\", \"model\": \"Mistral-7B-Instruct-v0.3\"}, \"completed_at\": \"2026-05-19T01:15:51.422Z\"}, \"exp-053\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:20:18.405Z\", \"updated_at\": \"2026-05-19T01:05:00.000Z\", \"hypothesis\": \"Seed replication of exp-033: the +4.90pp improvement on FOLIO-204 with Mistral-7B using symbolic invariant consensus (K=12) is reproducible across different random seeds, confirming the result is not a statistical fluke.\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 456 --math-data data/empty.json --pw-data data/empty.json --strategyqa-data data/empty.json --folio-data data/folio_full.json --output results/exp053_mistral_folio204_seed456/exp053_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 456}, \"metrics\": {\"n\": 204, \"sc_accuracy\": 56.37, \"sica_accuracy\": 55.88, \"sc_correct\": 115, \"sica_correct\": 114, \"delta_pp\": -0.49, \"discordant_b\": 2, \"discordant_c\": 3, \"extraction_rate\": 0.97, \"contradiction_rate\": 0.033, \"wall_time_min\": 80.8, \"mcnemar_p\": 1.0, \"significant\": false}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T01:02:00.000Z\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp053_mistral_folio204_seed456/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp053_mistral_folio204_seed456/exp053.log\", \"notes\": \"Seed=456: SICA=55.88% vs SC=56.37%, delta=-0.49pp, b=2, c=3, p=1.0. SC baseline 最高，capability trap 确认。跨 seed SC vs delta Pearson r=-0.8973。\", \"parent\": \"exp-033\"}, \"exp-050b-mistral-icl-oracle\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:31:50.554Z\", \"updated_at\": \"2026-05-18T23:19:54.810Z\", \"hypothesis\": \"Increasing vLLM max_model_len from 8192 to 16384 will resolve the context length overflow (input ~4400 + max_tokens 4096 > 8192) that caused 86% failure in exp-050, allowing Mistral-7B ICL Oracle with 5 gold FOL examples to complete evaluation on all 199 FOLIO problems.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 16384 --gpu-memory-utilization 0.90 --port 8002 --dtype auto --trust-remote-code --enforce-eager && python -u run_icl_oracle.py --api-base http://localhost:8002/v1 --model auto --k 12 --data data/folio_full.json --output results/exp050b_mistral_icl_oracle/exp050b_results.json --seed 42 --save-intermediates --temperature 0.7 --max-tokens 4096\", \"server\": \"westd-16639\", \"gpu_ids\": [\"cuda:2\"], \"data_path\": \"data/folio_full.json\", \"data_count\": 199, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"data/folio_full.json\"}, \"log_path\": \"/root/symb_invariant_consensus/results/exp050b_mistral_icl_oracle/exp050b.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp050b_mistral_icl_oracle/\", \"metrics\": {\"n\": 199, \"sc_accuracy\": 57.79, \"sica_accuracy\": 54.27, \"delta_pp\": -3.52, \"sc_correct\": 115, \"sica_correct\": 108, \"discordant_b\": 6, \"discordant_c\": 13, \"mcnemar_p\": 0.167, \"significant\": false, \"wall_time_min\": 93.8, \"extraction_success\": 2333, \"extraction_fail\": 55, \"per_answer\": {\"True\": {\"n\": 70, \"sica_acc\": 50, \"sc_acc\": 54.29}, \"False\": {\"n\": 61, \"sica_acc\": 36.07, \"sc_acc\": 44.26}, \"Unknown\": {\"n\": 68, \"sica_acc\": 75, \"sc_acc\": 73.53}}}, \"conclusion\": \"negative\", \"notes\": \"ICL Oracle (5 gold FOL examples) on Mistral-7B FOLIO-199: SICA=54.27% vs SC=57.79%, delta=-3.52pp (p=0.167, ns). ICL boosted SC from vanilla 54.41% (exp-033) to 57.79% (+3.38pp), but SICA did not benefit. ICL improves individual trace quality enough to boost majority vote, but the resulting constraints become less diverse/discriminative for MaxSAT weighting. Confirms capability trap: better extraction quality does not translate to SICA gains when it also reduces beneficial disagreement.\", \"completed_at\": \"2026-05-18T23:16:14.227Z\"}, \"exp-050-mistral-icl-oracle-folio199\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:48:25.841Z\", \"updated_at\": \"2026-05-18T23:19:53.802Z\", \"hypothesis\": \"Providing 5 gold FOL annotations as in-context learning examples will significantly improve the quality of symbolic constraint extraction from Mistral-7B reasoning traces, leading to higher SICA accuracy over SC baseline on FOLIO-199\", \"spec\": {\"command\": \"python -u run_icl_oracle.py --api-base http://localhost:8002/v1 --model auto --k 12 --data data/folio_full.json --output results/exp050_mistral_icl_oracle_folio199/exp050_results.json --seed 42 --save-intermediates --resume\", \"server\": \"westd-16639\", \"gpu_ids\": [\"cuda:2\"], \"data_path\": \"data/folio_full.json\", \"data_count\": 199, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"description\": \"ICL Oracle experiment: 5 gold FOL annotations as few-shot examples for constraint extraction, evaluate SICA vs SC on remaining 199 FOLIO problems\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T23:19:53.802Z\"}, \"exp-049b-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:53:09.676Z\", \"updated_at\": \"2026-05-18T23:16:15.080Z\", \"hypothesis\": \"Mistral-7B LogiQA-200 v2: 修复 exp-049 部署失败（vLLM 启动但 pipeline 未运行，tmux session 丢失）。验证 Mistral 的 +4.90pp FOLIO 增益是否跨 LogiQA 复现。parent=exp-033\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/run_exp049b.sh\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"gpu_ids\": [\"cuda:3\"], \"port\": 8003, \"tmux_session\": \"exp049b\", \"vllm_version\": \"0.21.0\", \"output_dir\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200\", \"log_path\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200/exp049b.log\", \"vllm_log\": \"/tmp/vllm_exp049b.log\", \"params\": {\"k\": 12, \"temperature\": 0.7, \"max_tokens\": 4096, \"max_model_len\": 8192, \"gpu_memory_utilization\": 0.9, \"enforce_eager\": true, \"VLLM_USE_FLASHINFER_SAMPLER\": 0}}, \"log_path\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200/exp049b.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200/\", \"metrics\": {\"n\": 200, \"sc_accuracy\": 51, \"sica_accuracy\": 51.5, \"delta_pp\": 0.5, \"sc_correct\": 102, \"sica_correct\": 103, \"discordant_b\": 6, \"discordant_c\": 5, \"mcnemar_p\": 1, \"significant\": false, \"wall_time_min\": 78.6, \"extraction_rate\": 0.9725, \"total_constraints\": 10659, \"unique_constraints\": 8934, \"contradiction_rate\": 0.0196}, \"conclusion\": \"negative\", \"notes\": \"Mistral-7B LogiQA-200: SICA=51.50% vs SC=51.00%, delta=+0.50pp (p=1.000, ns). Mistral's +4.90pp FOLIO advantage (exp-033) does not transfer to LogiQA. SC baseline 51% is near random for 4-choice MCQ. Consistent with exp-038 (14B LogiQA delta=-0.50pp): SICA provides no benefit on LogiQA regardless of model, likely because LogiQA's pragmatic reasoning resists symbolic constraint formalization.\", \"completed_at\": \"2026-05-18T23:16:15.080Z\"}, \"exp-044b-icl-oracle\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:16:44.204Z\", \"updated_at\": \"2026-05-18T22:59:34.846Z\", \"hypothesis\": \"ICL with Oracle Examples (v2, 正确模型 Qwen2.5-14B): 用 5 个 gold FOL annotations 作为 few-shot examples 教 LLM 提取高质量约束。如果 extraction quality 是 capability trap 瓶颈，oracle-guided extraction 应能产生更 discriminative 的约束，使 ICL-SICA > vanilla SICA (74.51%)。评测 199 题。v1 因使用错误模型 (Mistral-7B) 被 kill。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-18T20:17:35.899Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp044b_icl_oracle_qwen14b && CUDA_VISIBLE_DEVICES=0 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8000 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp044b.log 2>&1 & sleep 120 && python -u run_icl_oracle.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --data data/folio_full.json --output results/exp044b_icl_oracle_qwen14b/results.json --save-intermediates 2>&1 | tee results/exp044b_icl_oracle_qwen14b/exp044b.log\\\"\", \"finished_at\": \"2026-05-18T22:57:51.205Z\", \"training_hours\": 2.67}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp044b_icl_oracle_qwen14b && CUDA_VISIBLE_DEVICES=0 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8000 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp044b.log 2>&1 & sleep 120 && python -u run_icl_oracle.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --data data/folio_full.json --output results/exp044b_icl_oracle_qwen14b/results.json --save-intermediates 2>&1 | tee results/exp044b_icl_oracle_qwen14b/exp044b.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"95429\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044b-icl-oracle.log\", \"submitted_at\": \"2026-05-18T20:17:38.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9716.3, \"gpu_hours\": 2.7}, \"pid\": \"95429\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044b-icl-oracle.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T22:57:54.590178+00:00\"}]}, \"metrics\": {\"n\": 199, \"dataset\": \"FOLIO-199\", \"model\": \"Qwen2.5-14B-Instruct\", \"k\": 12, \"sica_accuracy\": 74.87, \"sc_accuracy\": 74.37, \"delta_pp\": 0.5, \"sica_correct\": 149, \"sc_correct\": 148, \"icl_examples\": 5, \"extraction_failure_rate\": 0.008}, \"conclusion\": \"negative\", \"checkpoint_path\": \"westd-25068:/root/symb_invariant_consensus/results/exp044b_icl_oracle_qwen14b/results.json\", \"completed_at\": \"2026-05-18T22:59:34.846Z\"}, \"exp-049-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:30:34.577Z\", \"updated_at\": \"2026-05-18T21:53:04.043Z\", \"hypothesis\": \"Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral delta=+4.90pp (exp-033, p=0.013)。14B 在 LogiQA 上 delta=-0.50pp (exp-038)。测试 regime boundary：Mistral 低 SC + 高 diversity 是否在 LogiQA 上也产生正向 SICA delta。parent=exp-033\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --output results/exp049_mistral_logiqa200/exp049_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"gpu_ids\": [\"cuda:3\"], \"tmux_session\": \"exp049\", \"output_dir\": \"results/exp049_mistral_logiqa200\", \"log_path\": \"results/exp049_mistral_logiqa200/exp049.log\", \"vllm_log\": \"/tmp/vllm_exp049.log\", \"port\": 8003}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T21:53:04.043Z\"}, \"exp-041-14b-folio204-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:33.016Z\", \"updated_at\": \"2026-05-18T21:08:19.597Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 FOLIO-204 上 SICA vs SC（westd-16639 独立重跑）：在不同服务器上复现 exp-001/026 结果，验证 capability trap 的可复现性和排除服务器环境差异。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --pw-data data/empty.json --folio-data data/folio_full.json --math-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"FOLIO-204\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T20:15:00.713Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T20:15:02.129Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T20:15:05.317649+00:00\"}]}, \"metrics\": {\"n\": 204, \"dataset\": \"FOLIO-204\", \"model\": \"Qwen2.5-14B-Instruct\", \"k\": 12, \"sica_accuracy\": 75.49, \"sc_accuracy\": 77.45, \"delta_pp\": -1.96, \"sica_correct\": 154, \"sc_correct\": 158, \"mcnemar_discordant_b\": 0, \"mcnemar_discordant_c\": 4, \"mcnemar_p_value\": 0.125, \"extraction_rate\": 0.98, \"contradiction_rate\": 0.0097}, \"log_path\": \"/root/symb_invariant_consensus/results/exp036_qwen25_14b_folio204/exp036.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp036_qwen25_14b_folio204/results.json\"}, \"exp-045b-backward-verify\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:16:45.453Z\", \"updated_at\": \"2026-05-18T20:30:28.631Z\", \"hypothesis\": \"Backward Verification v2 (正确模型 Qwen2.5-14B): 翻转验证方向，对每个候选答案反向推理 premises，用 Z3 检查一致性。v1 使用错误模型 (Qwen-7B) 得到 -21pp，需确认 Qwen-14B 上是否仍为强 negative（预期是，因为根因是 FOL quality 而非 model capacity）。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-18T20:17:45.787Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp045b_backward_qwen14b && CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp045b.log 2>&1 & sleep 120 && python -u backward_verification.py --api-base http://localhost:8003/v1 --model auto --k 12 --data data/folio_full.json --output results/exp045b_backward_qwen14b/results.json --seed 42 --temperature 0.7 2>&1 | tee results/exp045b_backward_qwen14b/exp045b.log\\\"\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp045b_backward_qwen14b && CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp045b.log 2>&1 & sleep 120 && python -u backward_verification.py --api-base http://localhost:8003/v1 --model auto --k 12 --data data/folio_full.json --output results/exp045b_backward_qwen14b/results.json --seed 42 --temperature 0.7 2>&1 | tee results/exp045b_backward_qwen14b/exp045b.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"95988\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045b-backward-verify.log\", \"submitted_at\": \"2026-05-18T20:17:47.319Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 761.3, \"gpu_hours\": 0.21}, \"pid\": \"95988\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045b-backward-verify.log\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-18T20:30:28.631Z\"}, \"exp-045-backward-verification\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:01:40.541Z\", \"updated_at\": \"2026-05-18T20:30:00.573Z\", \"hypothesis\": \"Backward Verification: 翻转验证方向，对每个候选答案反向推理需要哪些 premises 成立/矛盾，用 Z3 检查哪个答案与 premises 最一致（矛盾最少）。如果 forward extraction 质量是瓶颈，backward verification 绕过 extraction 直接用 solver 判断一致性，可能打破 capability trap。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-18T19:16:32.740Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_backward_verification.sh 3 8003\\\"\", \"finished_at\": \"2026-05-18T19:41:02.660Z\", \"training_hours\": 0.41}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_backward_verification.sh 3 8003\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"83115\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045-backward-verification.log\", \"submitted_at\": \"2026-05-18T19:16:34.043Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4146.5, \"gpu_hours\": 1.15}, \"pid\": \"83115\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045-backward-verification.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:41:05.769423+00:00\"}]}, \"conclusion\": \"negative\", \"notes\": \"v1: 可能使用了 Qwen-7B 残留 vLLM (exp-035 遗留 port 8003)。BV=53.92% vs SC=75.00%, delta=-21.08pp。Z3 SAT rate 95.3%=无判别力。True bias 72.5% vs gold 35.3%。根因：backward FOL generation 质量同样差，验证方向不解决 capability trap。即使换正确模型 (-21pp 幅度过大) 可能仍 negative。建议 Director 决策是否用 Qwen2.5-14B 重跑 v2。\", \"completed_at\": \"2026-05-18T20:25:40.512Z\"}, \"exp-038-14b-logiqa200-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:33.795Z\", \"updated_at\": \"2026-05-18T20:27:39.296Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 LogiQA 2.0 (200题) 上 SICA vs SC：跨数据集验证 capability trap。LogiQA 是多选逻辑推理（非二元分类），constraint extraction 和 Z3 formalization 需要适配不同推理类型。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --folio-data data/empty.json --math-data data/empty.json --pw-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"LogiQA-200\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp038_qwen25_14b_logiqa200/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp038_qwen25_14b_logiqa200/exp038.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T20:07:36.880Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T20:07:38.091Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T20:07:40.768677+00:00\"}]}, \"metrics\": {\"n\": 200, \"dataset\": \"LogiQA-200\", \"model\": \"Qwen2.5-14B-Instruct\", \"k\": 12, \"sica_accuracy\": 78, \"sc_accuracy\": 78.5, \"delta_pp\": -0.5, \"mcnemar_p\": 1, \"sica_correct\": 156, \"sc_correct\": 157, \"discordant_b\": 1, \"discordant_c\": 2, \"both_correct\": 155, \"both_wrong\": 42, \"extraction_rate\": 0.864, \"fail_empty_rate\": 0.122, \"avg_unique_constraints\": 26.7, \"contradiction_rate\": 0.008, \"wall_time_min\": 126.8}, \"notes\": \"实验成功完成200/200题，之前被自动监控误判为failed。结果：SICA略逊于SC(-0.5%)，McNemar p=1.0完全不显著。仅3例disagreement(sica_only=1, sc_only=2)。extraction_rate=86.4%低于FOLIO实验(~90%+)，fail_empty=12.2%较高——LogiQA的非形式化推理对constraint extraction更难。contradiction_rate仅0.8%，几乎无矛盾检测。结论：SICA在LogiQA非形式逻辑推理上无增益，capability trap假设在此数据集上未验证。\"}, \"exp-033\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:42:09.819Z\", \"updated_at\": \"2026-05-18T20:25:06.703Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=0 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8000 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp033.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp033_mistral_7b_folio204/exp033_results.json --save-intermediates 2>&1 | tee results/exp033_mistral_7b_folio204/exp033.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"65773\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-033.log\", \"submitted_at\": \"2026-05-18T17:42:09.638Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"wall_clock_seconds\": 5875.8, \"gpu_hours\": 1.63}, \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 FOLIO-204 全量上 SICA vs SC。验证 capability trap 跨模型家族在 full dataset 上是否持续（D012 pilot exp-010 已确认 delta=0, n=60）。\", \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:16.294Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:18.863472+00:00\"}]}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp033_mistral_7b_folio204/exp033_results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-033.log\", \"metrics\": {\"n_problems\": 204, \"sica_accuracy\": 59.31, \"sc_accuracy\": 54.41, \"delta_pp\": 4.9, \"sica_correct\": 121, \"sc_correct\": 111, \"mcnemar_discordant_b\": 12, \"mcnemar_discordant_c\": 2, \"mcnemar_p_value\": 0.0129, \"c0_non_unanimous_rate\": 0.8137, \"avg_majority_frac\": 0.7515, \"extraction_rate\": 97.14, \"contradiction_rate\": 3.5, \"problems_with_contradictions\": 128, \"avg_unique_constraints\": 39.3, \"maxsat_mean_sat_ratio\": 0.9609, \"total_constraints\": 14042, \"unique_constraints\": 8021, \"wall_time_min\": 81.4, \"k\": 12}, \"conclusion\": \"success\", \"notes\": \"Mistral-7B FOLIO-204: SICA 59.31% vs SC 54.41%, delta=+4.90pp (McNemar p=0.013, significant). 首次 SICA 显著超越 SC。关键因素：C0=81.37%（远高于 Qwen-7B 的 55%），高 diversity 使 SC majority vote 退化，而 SICA MaxSAT 仍能从 noisy traces 中提取信号。Discordant: SICA-only=12, SC-only=2, 高度不对称。但绝对准确率低（59% vs Qwen-7B 77%），说明 Mistral-7B 基础推理能力弱。结论：capability trap 非普遍现象，依赖 diversity/quality 平衡——高 diversity + 低 quality 时 SICA 有优势。\", \"completed_at\": \"2026-05-18T19:20:05.477Z\"}, \"exp-042b-premise-formal\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:13:55.356Z\", \"updated_at\": \"2026-05-18T20:10:14.058Z\", \"hypothesis\": \"Premise-Only Formalization (重启): 绕过 CoT trace extraction，直接让 LLM 将 FOLIO premises + conclusion 形式化为 FOL，用 Z3 验证逻辑蕴含。K=12 独立 formalization + majority vote。如果 extraction quality 是 capability trap 的瓶颈，直接 formalization 应能产生更准确的约束，使 Premise-FOL > vanilla SICA。exp-042 因 vLLM 未启动失败，本次重启。\", \"parent\": \"exp-042-premise-formalization\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-18T19:16:36.261Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_premise_formalization.sh 2 8002\\\"\", \"finished_at\": \"2026-05-18T19:19:15.214Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_premise_formalization.sh 2 8002\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"83150\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-042b-premise-formal.log\", \"submitted_at\": \"2026-05-18T19:16:37.520Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 159.8, \"gpu_hours\": 0.04}, \"pid\": \"83150\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-042b-premise-formal.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T19:19:17.277Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:19:19.962160+00:00\"}]}, \"notes\": \"失败根因：run_premise_formalization.sh 参数顺序是 PORT GPU，但调用传了 GPU PORT (2 8002)，导致 CUDA_VISIBLE_DEVICES=8002 → NVMLError_InvalidArgument。vLLM 未启动，0 题完成。将在 cleanup Worker 中用显式命令重部署。\"}, \"exp-044-icl-oracle\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:01:36.630Z\", \"updated_at\": \"2026-05-18T19:54:58.560Z\", \"hypothesis\": \"ICL with Oracle Examples: 用 5 个 gold FOL annotations 作为 few-shot examples 教 LLM 提取高质量约束。如果 extraction quality 是 capability trap 瓶颈，oracle-guided extraction 应能产生更 discriminative 的约束，使 ICL-SICA > vanilla SICA (74.51%)。评测 199 题（排除 5 个 ICL examples）。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-18T19:16:29.159Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_icl_oracle.sh 0 8000\\\"\", \"finished_at\": \"2026-05-18T19:52:18.717Z\", \"training_hours\": 0.6}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_icl_oracle.sh 0 8000\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"83086\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044-icl-oracle.log\", \"submitted_at\": \"2026-05-18T19:16:30.455Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2150.0, \"gpu_hours\": 0.6}, \"pid\": \"83086\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044-icl-oracle.log\", \"conclusion\": \"failed\", \"notes\": \"v2 失败: vLLM server 连接中断 (httpx.ConnectError: All connection attempts failed)，EXIT_CODE=129 (SIGHUP)。实验跑完但数据无效：extraction 成功率仅 17.1% (307/1800, 1490 json_fail)，SC=46.23% 远低于 Qwen2.5-14B 预期 75.49%。结果不可用，需在 vLLM 稳定后重跑。worker_infra_westd25068-gpu-cleanup-redeploy 正在处理 westd-25068 基础设施。\", \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-18T19:52:20.440Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:52:23.050199+00:00\"}]}}, \"exp-035\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:02:20.251Z\", \"updated_at\": \"2026-05-18T19:07:57.772Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 FOLIO-204 上 SICA vs SC：within-family scaling 下界验证。弱模型 C0 更高（更多 diversity），但 constraint quality 更差，SICA 仍无法 outperform SC。与 exp-004-qwen7b (D012 delta=0) 在 full FOLIO 上的扩展验证。代替原 ARC-60 实验（exp-035 v1 因平台 kill 失败）。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-7B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp035.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp035_qwen25_7b_folio204/exp035_results.json --save-intermediates 2>&1 | tee results/exp035_qwen25_7b_folio204/exp035.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"66133\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-035.log\", \"submitted_at\": \"2026-05-18T17:42:16.264Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 5136.9, \"gpu_hours\": 1.43}, \"conclusion\": \"negative\", \"notes\": \"v2 完成: Qwen2.5-7B FOLIO-204, 203/204题有结果(1题缺失)。JSON summary是stale的(n=195时计算)，实际数据从results数组203条计算。SICA与SC仅3个discordant pairs，几乎完全一致。假设验证：SICA无法outperform SC on 7B，delta=-0.49pp (p=1.0)。C0=0.55高于14B但未能转化为SICA优势。注意7B SC(77.34%)意外高于14B SC(75.49%)，可能因FOLIO数据特性。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp035_qwen25_7b_folio204/exp035_results.json\", \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:21.579Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:26.794237+00:00\"}]}, \"log_path\": \"~/runs/symb_invariant_consensus/exp-035.log\", \"metrics\": {\"n_problems\": 203, \"sc_accuracy\": 77.34, \"sica_accuracy\": 76.85, \"delta_pp\": -0.49, \"sica_correct\": 156, \"sc_correct\": 157, \"mcnemar_discordant_b\": 1, \"mcnemar_discordant_c\": 2, \"mcnemar_p_value\": 1, \"c0_non_unanimous_rate\": 0.5517, \"extraction_rate\": 98.19, \"contradiction_rate\": 1.58, \"problems_with_contradictions\": 60, \"total_constraints\": 12950, \"unique_constraints\": 6515, \"dedup_ratio\": 50.3, \"wall_time_min\": 78.2, \"avg_per_problem_s\": 23.1}, \"completed_at\": \"2026-05-18T19:07:53.139Z\"}, \"exp-036b-cross-trace-unsat\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:04:24.962Z\", \"updated_at\": \"2026-05-18T19:04:55.982Z\", \"hypothesis\": \"Cross-trace UNSAT: 合并不同候选答案的 constraints，检查 answer_A 与 answer_B 的约束是否 UNSAT（矛盾）。预期 cross-answer 对比的 UNSAT rate 远高于 within-trace 检查，因为不同答案的约束应该矛盾。如果 UNSAT 信号强，可用于增强 SICA 打分的 discriminative power。\", \"spec\": {\"command\": \"python3 cross_trace_unsat.py\", \"server\": \"westd-25068\", \"data_path\": \"results/folio_204_14b/\", \"data_count\": 204, \"model_name\": \"N/A (CPU-only, reuses exp-001 constraints)\", \"seed\": 42, \"checkpoint_source\": \"exp-001/folio_204_14b intermediates\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp036b_cross_trace_unsat.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp036b_cross_trace_unsat.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"cross_unsat_rate_pair\": 0.087, \"cross_unsat_rate_problem\": 0.107, \"within_trace_unsat_rate\": 0.009, \"unsat_pairs\": 11, \"total_pairs\": 126, \"problems_with_unsat\": 9, \"multi_answer_problems\": 84, \"single_answer_skip\": 120, \"zero_shared_var_pairs_pct\": 0.564, \"avg_shared_vars\": 2.7, \"false_true_unsat_rate\": 0.467, \"sica_cross_ut_accuracy\": 0.745, \"sc_accuracy\": 0.75, \"accuracy_impact\": 0}, \"completed_at\": \"2026-05-18T19:04:50.035Z\", \"notes\": \"Cross-trace UNSAT 验证了 Director 假设：cross-answer UNSAT rate (8.7%) 约为 within-trace (0.9%) 的 10x。但主要瓶颈是 Z3 变量命名不一致：56.4% 的 answer pairs 共享零变量，Z3 无法跨 trace 比较。False-True 对最具辨别力 (non-empty 中 46.7% UNSAT)。最终对准确率无影响（仅覆盖 9/204 问题），第 6 个 negative constructive。核心诊断价值：变量命名不一致是 capability trap 的关键机制之一。\"}, \"exp-042-premise-formalization\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:53:36.547Z\", \"updated_at\": \"2026-05-18T19:02:37.081Z\", \"hypothesis\": \"Premise-Only Formalization: 绕过 CoT trace extraction，直接让 LLM 将 FOLIO premises + conclusion 形式化为 FOL，用 Z3 验证逻辑蕴含。K=12 独立 formalization + majority vote。如果 extraction quality 是 capability trap 的瓶颈，直接 formalization 应能产生更准确的约束，使 Premise-FOL > vanilla SICA。\", \"spec\": {\"command\": \"premise_formalization.py --api-base http://localhost:8002/v1 --model auto --k 12 --data data/folio_full.json --output results/exp042_premise_formalization/results.json --seed 42\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-042-premise-formalization.log\", \"submitted_at\": \"2026-05-18T18:53:44.005Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 533.1, \"gpu_hours\": 0.15}, \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:34.758Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T19:02:37.081Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:40.161215+00:00\"}]}}, \"exp-043-consistency-filtering\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:58:40.028Z\", \"updated_at\": \"2026-05-18T18:59:10.069Z\", \"hypothesis\": \"Constraint Consistency Filtering: 从已有 exp-001 数据中，只保留在 ≥T/K 条 trace 中出现的约束（T=4,6,8），用筛选后的约束跑 MAX-SAT。假设跨 trace 一致出现的约束质量更高，filtered SICA > full SICA。\", \"spec\": {\"command\": \"python3 run_consistency_filtering.py\", \"server\": \"westd-25068\", \"data_path\": \"results/folio_204_14b/\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct (reuse exp-001 data)\", \"seed\": 42, \"checkpoint_source\": \"exp-001/folio_204_14b intermediates\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp4_consistency_filtering/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp4_consistency_filtering/results.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.75, \"sica_t1_all\": 0.7794, \"sica_t4\": 0.75, \"sica_t6\": 0.7549, \"sica_t8\": 0.7549, \"avg_unique_constraints\": 13.2, \"avg_filtered_t4\": 1.8, \"avg_filtered_t6\": 0.8, \"avg_filtered_t8\": 0.3}, \"completed_at\": \"2026-05-18T18:59:04.105Z\", \"notes\": \"Consistency filtering NEGATIVE: 过滤后约束数量骤降（T≥4 仅 1.8/题, T≥8 仅 0.3/题），MaxSAT 无法区分答案，退化为 SC。根因：Z3 变量命名不一致导致语义等价约束被视为不同（avg 13.2 unique constraints/problem），跨 trace 一致性极低。第 5 个 negative constructive intervention。注意：T=1 的 77.94% 与 exp-001 的 74.51% 差异是已知 pipeline 非确定性问题（code path confound）。\"}, \"exp-036-z3-feedback-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:18:09.052Z\", \"updated_at\": \"2026-05-18T18:53:05.656Z\", \"hypothesis\": \"Z3 UNSAT core feedback refinement: closed-loop 方法用 Z3 solver 的 UNSAT core 指导 LLM 修正矛盾约束（最多 3 轮）。如果约束质量是瓶颈，solver 反馈应能提升 constraint discriminative power，使 Z3-feedback SICA > vanilla SICA。目标 recovery_rate > 0%（recovery_rate = Z3fb_delta / oracle_delta × 100%）。与之前 open-loop interventions（contrastive/cross-model/generational 全部失败）对比，closed-loop 利用 formal verification 信号可能是打破 capability trap 的关键。\", \"spec\": {\"command\": \"python3 run_z3_feedback_folio.py --api-base http://localhost:8002/v1 --model auto --traces-dir results/folio_204_14b --max-rounds 3 --output-dir results/exp036_z3_feedback --K 12 --T-ext 0.3\", \"server\": \"westd-25068\", \"data_path\": \"results/folio_204_14b/\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pre-computed traces from exp-001/folio_204_14b\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp036_z3_feedback/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp036_z3_feedback/z3_feedback.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T18:52:57.206Z\", \"notes\": \"Z3 feedback mechanism had zero real impact. Apparent +3.0pp (77.5% vs 74.5%) entirely due to code path confound: JSON serialization vs in-memory processing caused different dedup/scoring behavior. UNSAT trigger rate 0.9% (22/2448 traces), too low for feedback loop to meaningfully activate. All observed delta on discordant problems came from pipeline non-determinism, not Z3 refinement. Fourth negative constructive intervention after contrastive, cross-model, generational.\", \"metrics\": {\"z3fb_sica_accuracy\": 0.775, \"vanilla_sica_accuracy\": 0.745, \"sc_accuracy\": 0.75, \"z3fb_vs_vanilla_delta\": 0.03, \"unsat_traces\": 22, \"total_traces\": 2448, \"unsat_rate\": 0.009, \"unsat_resolve_rate\": 0.864, \"problems_flipped\": 0, \"real_impact\": 0}}, \"exp-028-qwen3-14b-thinking\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:02:12.168Z\", \"updated_at\": \"2026-05-18T18:06:48.306Z\", \"hypothesis\": \"Qwen3-14B thinking mode 在 FOLIO 204 上 SICA vs SC：原生推理能力（内置 CoT）是否改变 capability trap？两种可能：(a) thinking mode 使 traces 更确定性（类似 QwQ-32B），C0 极低→SICA≡SC；(b) thinking mode 提升 constraint extraction 质量，打破 capability trap。预期 (a) 更可能。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_qwen3_14b_thinking.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"40990\", \"log_path\": \"/root/symb_invariant_consensus/results/exp028_qwen3_14b_thinking/exp028.log\", \"submitted_at\": \"2026-05-18T14:21:40.871Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-14B (HuggingFace)\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp028_qwen3_14b_thinking/\", \"wall_clock_seconds\": 13499.2, \"gpu_hours\": 3.75}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-18T18:06:40.098Z\", \"notes\": \"Killed per D049: extraction_rate 73% below 80% threshold. Partial results (35/204): SICA 88.57%, SC 85.71%, delta +2.86pp. But extraction_rate degrading and ETA 16h+ made continued run not worthwhile. GPU freed for D050 constructive experiments.\"}, \"exp-033-qwen3-pw600-nonthinking\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:01:55.209Z\", \"updated_at\": \"2026-05-18T18:00:09.156Z\", \"hypothesis\": \"Qwen3-14B in non-thinking mode on ProofWriter 600 will show whether SICA's constraint-based consensus improves over SC@K for a model without chain-of-thought reasoning overhead, providing a controlled comparison against thinking-mode results.\", \"spec\": {\"command\": \"bash scripts/run_exp033_qwen3_pw600.sh\", \"server\": \"westd-16639 (via westd-25068)\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 42, \"gpu\": \"cuda:1 (NVIDIA RTX PRO 6000 Blackwell 97GB)\", \"port\": 8001, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 4096, \"max_model_len\": 8192, \"enable_thinking\": false, \"tmux_session\": \"exp033\", \"output_dir\": \"results/qwen3_14b_pw600_nonthinking/\", \"log_path\": \"results/qwen3_14b_pw600_nonthinking/run.log\"}, \"conclusion\": \"failed\", \"notes\": \"FAILED: AutoDL 平台级 SIGTERM 导致 vLLM EngineCore 崩溃 (00:05:54)，后紧急清理 Worker 误杀 tmux server 连带终止。518/600 intermediates 有效可恢复。\", \"checkpoint_path\": \"westd-16639:/root/symb_invariant_consensus/results/qwen3_14b_pw600_nonthinking/intermediates/ (518/600, instance reset lost)\", \"completed_at\": \"2026-05-18T18:00:09.156Z\"}, \"exp-004-qwen7b-rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:16:48.010Z\", \"updated_at\": \"2026-05-18T18:00:08.383Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 D012 60 题上 SICA vs SC rerun（修复后代码）：弱模型 C0 更高（更多 diversity），但 constraint quality 更差，SICA 仍无法 outperform SC。验证 capability trap 在 within-family scaling 的下界。与之前 exp-004-qwen7b (delta=0) 对比验证一致性。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp004_7b_rerun.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"58035\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-004-qwen7b-rerun.log\", \"submitted_at\": \"2026-05-18T16:30:26.795Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_d012.json + data/proofwriter_d012.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-7B-Instruct\", \"eval_data\": \"D012 (30 FOLIO + 30 ProofWriter)\", \"wall_clock_seconds\": 5381.6, \"gpu_hours\": 1.49}, \"conclusion\": \"failed\", \"notes\": \"FAILED: ModelScope 下载失败，Qwen2.5-7B-Instruct 模型下载未完成。实验从未开始运行。需要 HF 镜像修复后重试。\", \"checkpoint_path\": \"N/A (download failed, never ran)\", \"completed_at\": \"2026-05-18T18:00:08.383Z\"}, \"exp-007-qwen72b-awq\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:16:47.099Z\", \"updated_at\": \"2026-05-18T18:00:07.574Z\", \"hypothesis\": \"Qwen2.5-72B-Instruct-AWQ (4-bit) 在 D012 60 题上 SICA vs SC：72B scaling 是否打破 capability trap？预期 SC baseline 更高（模型更强），但 SICA≈SC（extraction quality bottleneck 不随 model scale 改善），证明 scaling 不是 rescue path。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && bash /root/symb_invariant_consensus/scripts/run_exp007_72b_awq.sh\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"56225\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-007-qwen72b-awq.log\", \"submitted_at\": \"2026-05-18T16:21:30.961Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"D012 (30 FOLIO + 30 ProofWriter)\", \"data_count\": 60, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-72B-Instruct-AWQ (HuggingFace)\", \"eval_data\": \"D012 (30 FOLIO + 30 ProofWriter)\", \"wall_clock_seconds\": 5916.6, \"gpu_hours\": 1.64}, \"conclusion\": \"failed\", \"notes\": \"FAILED: HuggingFace 网络不通 (Network unreachable)，模型下载失败。72B AWQ 模型从未下载完成，实验从未开始运行。需要 HF 镜像修复后重试。\", \"checkpoint_path\": \"N/A (download failed, never ran)\", \"completed_at\": \"2026-05-18T18:00:07.575Z\"}, \"exp-027-qwen3-14b-non-thinking\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:02:11.425Z\", \"updated_at\": \"2026-05-18T17:58:11.787Z\", \"hypothesis\": \"Qwen3-14B（代际升级）在 non-thinking mode 下 FOLIO 204 的 SICA vs SC：capability trap 是否在次世代模型持续？预期 Qwen3 基础能力提升使 SC baseline 更高，但 self-extraction 质量仍不足以产生 SICA 增益（delta≈0），证明 capability trap 是结构性的而非模型能力不足。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_qwen3_14b_nonthinking.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:1\"], \"pid\": \"38106\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-027-qwen3-14b-non-thinking.log\", \"submitted_at\": \"2026-05-18T14:08:01.969Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-14B (HuggingFace)\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 13809.8, \"gpu_hours\": 3.84}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"k\": 12, \"sica_accuracy\": 0.8431, \"sc_accuracy\": 0.8382, \"delta_pp\": 0.49, \"extraction_rate\": 0.995, \"contradiction_rate\": 0.0283, \"problems_with_contradictions\": 69, \"total_constraints\": 16153, \"unique_constraints\": 7031, \"wall_time_s\": 11017, \"model\": \"Qwen3-14B\", \"dataset\": \"FOLIO-204\", \"mode\": \"non-thinking\"}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/qwen3_14b_folio204_nonthinking/\", \"notes\": \"Qwen3-14B non-thinking FOLIO-204: SICA 84.31% vs SC 83.82%, delta=+0.49pp。Qwen3 SC baseline 83.82% 远高于 Qwen2.5-14B 的 75.00% (+8.82pp)，证明 Qwen3 基础能力显著提升。但 SICA-SC gap 仍≈0 (+0.49pp)，capability trap 在次世代模型上持续。Extraction rate 99.5% (vs 14B 98.5%)，contradiction rate 2.83%。论文价值：(1) 证明 capability trap 是结构性的，非模型能力不足；(2) 代际升级提升 SC 不提升 SICA delta。\", \"completed_at\": \"2026-05-18T17:58:11.787Z\"}, \"exp-030-crossmodel-mistral-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:47:46.451Z\", \"updated_at\": \"2026-05-18T16:16:11.345Z\", \"hypothesis\": \"Cross-model extraction: Mistral-7B 从 Qwen2.5-14B 的 FOLIO 204 traces 中提取 constraints，能否打破 same-model capability trap？不同模型有不同的 extraction bias，Mistral 可能提取出 Qwen self-extraction 遗漏的 discriminative constraints。目标 discriminative_rate >8.2%（baseline），recovery_rate >0%。\", \"parent\": \"exp-026-folio204-trace-regen\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp030_crossmodel_mistral.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"46525\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-030-crossmodel-mistral-folio204.log\", \"submitted_at\": \"2026-05-18T14:50:47.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/intermediates/\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"exp-026-folio204-trace-regen\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 5123.4, \"gpu_hours\": 1.42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"k\": 12, \"crossmodel_sica_accuracy\": 0.75, \"sc_accuracy\": 0.75, \"delta_pp\": 0, \"discriminative_rate\": 0, \"recovery_rate\": 0, \"model_extraction\": \"Mistral-7B-Instruct-v0.3\", \"model_traces\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\"}, \"notes\": \"NEGATIVE. Cross-model extraction (Mistral-7B extracts constraints from Qwen2.5-14B traces) 完全无效：SICA = SC = 75.00%, discriminative_rate=0%, recovery_rate=0%. Mistral 虽然是不同模型家族，但提取的 constraints 同样缺乏判别力。这进一步强化 capability trap 结论：问题不在 same-model bias，而在 LLM extraction 本身的能力限制——无论哪个模型做 extraction，都无法从 CoT traces 中提取出对答案有判别力的 symbolic constraints。论文 claim: cross-model 不是 rescue path。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/cross_model_mistral_folio/\", \"completed_at\": \"2026-05-18T16:16:11.345Z\"}, \"exp-031-oracle-folio-regen\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:48:41.292Z\", \"updated_at\": \"2026-05-18T15:55:28.070Z\", \"hypothesis\": \"Oracle SICA with gold FOL annotations on exp-026 regenerated traces (post normalization-fix): if constraint quality is the bottleneck, replacing self-extracted constraints with gold FOL + Z3 entailment should significantly outperform SC and SICA(self), replicating exp-021's finding on fixed code.\", \"spec\": {\"command\": \"python scripts/run_exp031_oracle_folio_regen.py\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json + results/folio_204_14b/intermediates/\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct (traces) + Z3 (oracle constraints)\", \"seed\": 42, \"checkpoint_path\": \"results/oracle_folio_regen/exp031_results.json\", \"log_path\": \"results/oracle_folio_regen/exp031_summary.json\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"k\": 12, \"oracle_sica_accuracy\": 0.8971, \"sc_accuracy\": 0.7549, \"sica_self_accuracy\": 0.7451, \"oracle_vs_sc_delta_pp\": 14.22, \"oracle_vs_sica_delta_pp\": 15.2, \"mcnemar_p_oracle_vs_sc\": 2.0024e-07, \"mcnemar_b_c\": {\"b_oracle_right_sc_wrong\": 29, \"c_oracle_wrong_sc_right\": 0}, \"z3_gold_agreement\": 0.951, \"z3_gold_agree_n\": 194, \"z3_in_candidates_n\": 178, \"fol_parse_success\": 1, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\", \"constraint_source\": \"gold FOL annotations\", \"traces_source\": \"exp-026-folio204-trace-regen\"}, \"completed_at\": \"2026-05-18T15:49:32.164Z\", \"notes\": \"KEY RESULT. Oracle-SICA (gold FOL + Z3 entailment + consistency-weighted voting) 89.71% vs SC 75.49% vs SICA(self) 74.51%, +14.22pp over SC, McNemar p=2.0e-07 极显著, b=29 c=0 (oracle 从未输给 SC)。Z3 gold agreement 95.10% (194/204), FOL parser 204/204 全成功。Per-type: True 97.2% (+4.1pp), False 93.6% (+6.3pp), Unknown 78.3% (+31.9pp)。与 exp-021 (88.24%, 旧 traces) 对比：oracle 准确率从 88.24% 提升至 89.71%（+1.47pp），delta 从 +8.82pp 增至 +14.22pp。差异来源：(1) exp-026 traces 的 SC baseline 更低 (75.49% vs 79.41%)；(2) Z3 agreement 从 94.6% 提升至 95.1%。结论与 exp-021 一致：MAX-SAT 聚合机制有效——瓶颈在约束提取质量。\"}, \"exp-029-contrastive-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:22:03.513Z\", \"updated_at\": \"2026-05-18T15:38:58.925Z\", \"hypothesis\": \"Contrastive constraint extraction (answer-conditioned supporting/opposing constraints with structured JSON output and MaxSAT integration) will achieve discriminative_rate >20% (vs baseline 8.2%) and positive recovery_rate on FOLIO 204, because per-candidate opposing constraints provide stronger signal than simple majority voting for disambiguating closely-scored answers.\", \"parent\": \"exp-026-folio204-trace-regen\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && bash /root/symb_invariant_consensus/scripts/run_exp029_contrastive.sh'\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"42353\", \"log_path\": \"/root/symb_invariant_consensus/results/exp-029-contrastive-folio204/run.log\", \"submitted_at\": \"2026-05-18T14:24:26.683Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/intermediates/\", \"data_count\": 181, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"exp-026-folio204-trace-regen\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 4354.6, \"gpu_hours\": 1.21, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp-029-contrastive-folio204/contrastive_results.json\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"results/exp-029-contrastive-folio204/contrastive_results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-029-contrastive-folio204.log\", \"completed_at\": \"2026-05-18T15:37:01.319Z\", \"metrics\": {\"contrastive_accuracy\": 0.7253, \"sc_accuracy\": 0.7363, \"delta_pp\": -1.1, \"discriminative_rate\": 0.0604, \"discriminative_count\": 11, \"n\": 182, \"recovery_rate_pct\": -8.3, \"mcnemar_chi2\": 0.1, \"mcnemar_p\": 0.7518, \"cont_only_correct\": 4, \"sc_only_correct\": 6, \"both_correct\": 128, \"both_wrong\": 44, \"supporting_pct\": 43.2, \"opposing_pct\": 56.8, \"avg_constraints_per_problem\": 24.4, \"avg_unique_per_problem\": 10.4, \"wall_time_min\": 47.2}}, \"exp-026-folio204-trace-regen\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T11:41:13.054Z\", \"updated_at\": \"2026-05-18T14:46:34.862Z\", \"hypothesis\": \"FOLIO 204 全量 trace 重生成（Qwen2.5-14B, K=12, T=0.7 trace gen, T_ext=0.3 extraction）：在 westd-25068 上生成 FOLIO traces，用于 cross-model extraction 和 case study 选取。归一化 bug 已修复（startswith 方案），温度双参数已正确分离。\", \"parent\": \"sica_expanded_14b\", \"reproduce\": {\"finished_at\": \"2026-05-18T12:07:33.628Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-18T12:07:34.444Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T12:07:37.428043+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"bash scripts/run_folio_trace_regen.sh\", \"server\": \"westd-25068\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\"], \"pid\": 27245, \"log_path\": \"/root/symb_invariant_consensus/logs/folio_regen_v3_20260518_201127.log\", \"output_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/folio_204_results.json\", \"temperature_trace\": 0.7, \"temperature_extraction\": 0.3, \"K\": 12, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (HuggingFace)\", \"eval_data\": \"FOLIO-204 validation set\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"k\": 12, \"sica_accuracy\": 0.7451, \"sc_accuracy\": 0.7549, \"delta_pp\": -0.98, \"extraction_rate\": 0.9853, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\", \"temperature_trace\": 0.7, \"temperature_extraction\": 0.3, \"wall_time_h\": 2.5}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/\", \"notes\": \"FOLIO 204 全量 trace 重生成完成 (204/204)。SICA 74.51% vs SC 75.00%, delta=-0.49pp，与 sica_expanded_14b FOLIO 子集 (79.4%/79.4%, delta=0) 一致——capability trap 在重生成 traces 上仍成立。归一化 bug 修复 + 温度双参数分离后 extraction_rate=98.53% (vs 之前 89%)。Traces 已被 exp-029 contrastive 实验复用。结果路径: /root/symb_invariant_consensus/results/folio_204_14b/folio_204_results.json\"}, \"exp-023-discriminative-rate\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:50:26.792Z\", \"updated_at\": \"2026-05-18T04:44:24.397Z\", \"hypothesis\": \"Full-dataset discriminative rate analysis (W1+W3 合并): Qwen2.5-14B 在 804 题上 self-extracted constraints 的 source-trace discriminativeness 和 Z3 semantic discriminativeness 均低于 15%，证明即使用 Z3 per-answer evaluation，self-extracted constraints 仍无判别力，封堵 oracle scoring confound。\", \"parent\": \"sica_constraint_ablation_013\", \"spec\": {\"command\": \"python scripts/analyze_discriminative_rate.py\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/results/sica_expanded_14b.json\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": \"N/A\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/root/symb_invariant_consensus/results/discriminative_rate_analysis.json\", \"checkpoint_source\": \"sica_expanded_14b traces\", \"eval_data\": \"FOLIO 204 + ProofWriter 600 = 804\"}, \"metrics\": {\"n_total\": 804, \"n_multi_candidate\": 307, \"source_disc_rate_weight\": 0.392, \"source_disc_rate_weight_ci95\": [0.387, 0.398], \"source_disc_rate_count_est\": 0.121, \"source_disc_rate_count_ci95\": [0.12, 0.123], \"z3_semantic_disc_rate\": 0.082, \"z3_semantic_disc_ci95\": [0.076, 0.088], \"problems_with_disc\": 289, \"problems_with_disc_rate\": 0.941, \"pw_source_disc_weight\": 0.364, \"folio_source_disc_weight\": 0.54, \"pw_n_multi\": 235, \"folio_n_multi\": 72, \"pilot_rate_reported_count\": 0.115, \"pilot_rate_reported_weight\": 0.372, \"pilot_validation_weight\": 0.376, \"pilot_delta_pp\": 0.38, \"z3_answer_assertions\": 642, \"z3_total_unique_constraints\": 7844, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO+ProofWriter-804\"}, \"conclusion\": \"success\", \"notes\": \"Full 804-instance discriminative rate (R3 W1+W3, v1+v2 合并). By weight: 39.2% [38.7, 39.8]; by count (est): 12.1% [12.0, 12.3]. Z3 semantic disc: 8.2% [7.6, 8.8]. Per-domain: FOLIO 54.0% > PW 36.4% (by weight). 289/307 multi-candidate 问题有≥1 discriminative constraint (94.1%). Pilot validation: weight 37.6% vs 报告 37.2% (delta 0.38pp); count 12.1% vs 报告 11.5% (delta 0.6pp)——高度一致。v2 修复了 v1 的 assertion weight 不对称问题。数据: /root/symb_invariant_consensus/analysis/discriminative_rate_full_804.json\", \"completed_at\": \"2026-05-18T04:25:57.741Z\"}, \"exp-022-oracle-proofwriter\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:47:31.892Z\", \"updated_at\": \"2026-05-18T03:48:13.174Z\", \"hypothesis\": \"ProofWriter oracle: gold DSL (raw_logic_programs) 通过 Z3 consistency checking 加权 K=12 traces，Oracle-SICA 应显著超越 SC 和 SICA(self)，在 ProofWriter 600 题上复现 FOLIO oracle (+8.82pp) 的 extraction bottleneck 结论。\", \"parent\": \"exp-021-oracle-folio\", \"spec\": {\"command\": \"python scripts/run_exp022_oracle_proofwriter.py\", \"server\": \"westd-32608\", \"data_path\": \"/root/autodl-tmp/crdd/data/proofwriter/proofwriter-OWA-D5-validation.jsonl\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct (traces) + Z3 (oracle)\", \"seed\": \"N/A\", \"checkpoint_path\": \"N/A (CPU-only oracle)\", \"log_path\": \"/root/symb_invariant_consensus/results/exp022_oracle_pw.log\", \"checkpoint_source\": \"sica_expanded_14b traces (no model checkpoint)\", \"eval_data\": \"ProofWriter OWA-D5 validation 600 problems\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 600, \"k\": 12, \"oracle_sica_accuracy\": 0.8667, \"sc_accuracy\": 0.7517, \"sica_self_accuracy\": 0.755, \"oracle_vs_sc_delta_pp\": 11.5, \"mcnemar_p_oracle_vs_sc\": 9.21e-15, \"z3_gold_agreement\": 0.9714, \"z3_gold_agree_n\": 577, \"z3_gold_total\": 594, \"parse_errors\": 6, \"parse_error_rate\": 0.01, \"solver_errors\": 0, \"solver_total\": 7128, \"relneg_oracle\": 0.7786, \"relneg_sc\": 0.6, \"relneg_delta_pp\": 17.86, \"relnoneg_oracle\": 0.7945, \"relnoneg_sc\": 0.6644, \"relnoneg_delta_pp\": 13.01, \"attnoneg_oracle\": 0.961, \"attnoneg_sc\": 0.8701, \"attnoneg_delta_pp\": 9.09, \"attneg_oracle\": 0.9188, \"attneg_sc\": 0.85, \"attneg_delta_pp\": 6.87, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"ProofWriter-OWA-D5-600\", \"constraint_source\": \"gold DSL (raw_logic_programs)\"}, \"notes\": \"KEY RESULT. ProofWriter Oracle-SICA (gold DSL + Z3 + MAX-SAT) 86.67% vs SC 75.17% vs SICA(self) 75.50%, +11.50pp, McNemar p=9.21e-15 极显著。Z3 gold agreement 97.14% (577/594), parse errors 仅 6/600 (1%), solver errors 0/7128。Per-subtype: RelNeg +17.86pp > RelNoneg +13.01pp > AttNoneg +9.09pp > AttNeg +6.87pp——关系谓词（推理链更长）获益远大于属性谓词。与 FOLIO oracle (exp-021, +8.82pp, p=6.15e-5) 对比：ProofWriter delta 更大 (+11.50 vs +8.82) 且统计显著性高 6 个数量级。两个子域 Oracle 实验一致证明：MAX-SAT 聚合机制有效，瓶颈在 LLM self-extraction 质量。\", \"completed_at\": \"2026-05-18T03:48:13.174Z\"}, \"temperature-ablation-t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:03:05.890Z\", \"updated_at\": \"2026-05-17T19:11:20.157Z\", \"hypothesis\": \"Temperature ablation T=0.7 同源补跑：消除 T=0.7 数据来自不同 run (sica_d012_14b) 的混淆。预期 Δ=0（与 T=0.3/0.5/1.0 一致），C0 值可直接与其他温度点比较。\", \"parent\": \"temperature-ablation-t03\", \"spec\": {\"command\": \"bash /root/autodl-tmp/symb_invariant_consensus/scripts/run_temperature_ablation_t07.sh\", \"server\": \"westd-32608\", \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"tmux_session\": \"temperature-ablation-t07\"}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.7167, \"sc_accuracy\": 0.75, \"delta_pp\": -3.33, \"multi_candidate_rate\": 0.4, \"extraction_rate\": 0.9208, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.022, \"discordant_sica_wins\": 0, \"discordant_sc_wins\": 2, \"truncated_traces\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.7, \"proofwriter_sica\": 0.6333, \"proofwriter_sc\": 0.7, \"proofwriter_n\": 30, \"folio_sica\": 0.8, \"folio_sc\": 0.8, \"folio_n\": 30, \"wall_time_s\": 3498.3}, \"notes\": \"T=0.7 同源补跑完成（60/60 题）。C0=40.0%，介于 T=0.5(38.3%) 和 T=1.0(43.3%) 之间，消除了旧数据 T=0.7(53.3%) 来自不同 run 的混淆。四温度点 C0 现呈单调递增：T=0.3(30%) → T=0.5(38.3%) → T=0.7(40.0%) → T=1.0(43.3%)。SICA 71.67% < SC 75.00%，delta=-3.33pp，discordant 0:2（SC wins only）。FOLIO 80%=80%，PW SICA 63.33% < SC 70%。结论与其他温度点一致：diversity 增加但 constraint quality 无改善，delta≈0。\", \"conclusion\": \"negative\", \"log_path\": \"/root/runs/symb_invariant_consensus/sica_aime30_t07.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T0.7_results.json\", \"completed_at\": \"2026-05-17T19:11:20.157Z\"}, \"sica_constraint_ablation_013\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T20:26:35.414Z\", \"updated_at\": \"2026-05-17T18:38:00.543Z\", \"spec\": {\"command\": \"python scripts/extract_constraints_for_ablation.py\", \"server\": \"westd-32608\", \"data_path\": \"results/sica_expanded_14b/\", \"data_count\": 804, \"model_name\": \"N/A (CPU ablation on exp-001 outputs)\", \"seed\": \"N/A\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"results/constraint_ablation.json\", \"completed_at\": \"2026-05-16T20:26:58.473Z\", \"hypothesis\": \"exp-013: MaxSAT 加权聚合是否比 count-only 或 random-weight 有显著优势？验证 SICA 核心机制（约束加权）的实际贡献\", \"parent\": \"sica_expanded_14b\", \"metrics\": {\"maxsat_accuracy\": 0.7649, \"count_only_accuracy\": 0.7662, \"random_weight_accuracy\": 0.7587, \"sc_baseline_accuracy\": 0.7624, \"n_problems\": 804, \"maxsat_correct\": 615, \"count_only_correct\": 616, \"random_weight_correct\": 610, \"sc_correct\": 613, \"agreement_maxsat_vs_countonly\": \"803/804\", \"agreement_maxsat_vs_randomwt\": \"785/804\", \"agreement_maxsat_vs_sc\": \"773/804\", \"agreement_countonly_vs_randomwt\": \"786/804\", \"agreement_countonly_vs_sc\": \"774/804\", \"agreement_randomwt_vs_sc\": \"764/804\", \"mcnemar_p_all_gt_0.7\": true}, \"notes\": \"exp-013 constraint ablation 完成，数据已从 ablation_results.json 交叉验证。关键修正：(1) 802/804 不存在于任何 pairwise comparison，原 registry 数据错误；(2) random-weight accuracy 修正为 75.87% (610/804)，原 76.37% 是近似值。核心发现：MaxSAT vs Count-only 803/804 agreement 确认 SAT solver 无增量。MaxSAT vs SC 773/804 (31 disagreements, 16 SICA wins / 14 SC wins / 1 both wrong diff)——SICA 改了 31 题但 wins/losses 几乎抵消。数据文件：/root/symb_invariant_consensus/analysis/exp013_agreement_matrix.json\"}, \"exp-004-qwen7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T17:09:36.912Z\", \"updated_at\": \"2026-05-17T18:10:04.422Z\", \"hypothesis\": \"Within-family scaling: Qwen2.5-7B-Instruct 在 D012 60 题上 SICA vs SC。弱模型预期 C0 > 14B（更多 diversity），但 constraint quality 预期更低，SICA-SC gap 预期≈0——验证 capability trap 的 scaling 维度。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp004_qwen7b.sh\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/\", \"data_count\": 60, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"tmux_session\": \"exp-004-qwen7b\", \"checkpoint_source\": \"Qwen/Qwen2.5-7B-Instruct (base pretrained, symlink at /root/autodl-tmp/models/Qwen2.5-7B-Instruct)\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T17:55:15.007Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T17:55:15.926Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T17:55:18.762977+00:00\"}]}, \"notes\": \"Qwen2.5-7B within-family scaling: SICA=SC=68.33% (41/60), Δ=0.00pp, C0=43.3%, McNemar p=1.0。60 题全部完成（run.log 确认）。C0=43.3% 高于 14B 的 38.2%（弱模型更多 diversity），但 Δ=0 确认 capability trap 在 7B scale 同样成立。Discordant 2:2 完全对称。Per-domain: FOLIO SICA 76.7% vs SC 73.3% (+3.3pp), PW SICA 60.0% vs SC 63.3% (-3.3pp)，方向相反互相抵消。extraction_rate=94.2%。\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.6833, \"sc_accuracy\": 0.6833, \"delta_pp\": 0, \"multi_candidate_rate\": 0.433, \"extraction_rate\": 0.9417, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.0274, \"discordant_sica_wins\": 2, \"discordant_sc_wins\": 2, \"mcnemar_p\": 1, \"wall_time_s\": 1838, \"truncated_traces\": 0, \"model\": \"Qwen2.5-7B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.7, \"folio_sica\": 0.7667, \"folio_sc\": 0.7333, \"folio_n\": 30, \"proofwriter_sica\": 0.6, \"proofwriter_sc\": 0.6333, \"proofwriter_n\": 30}}, \"temperature-ablation-t10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:46:01.069Z\", \"updated_at\": \"2026-05-17T17:16:54.736Z\", \"hypothesis\": \"Temperature ablation T=1.0: 高温下 Qwen2.5-14B trace diversity 最大化（C0 预期>60%），SICA-SC gap 预期≈0 或负——验证最大 diversity 仍不能拯救 SICA，因为 constraint discriminative power 不随 diversity 增加\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_temperature_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T1.0_results.json\", \"log_path\": \"/tmp/temperature_ablation.log\"}, \"notes\": \"T=1.0 高温：C0=43.3%，低于 T=0.7 的 53.3%（注意：T=0.7 数据来自 sica_d012_14b 不同 run）。SICA=SC=75.00%，delta=0，discordant=0。最大温度仍不能拯救 SICA。Temperature ablation 结论：T=0.3(30%) → T=0.5(38.3%) → T=1.0(43.3%) 三点 C0 递增，但加上 T=0.7(53.3%, 来自 sica_d012_14b) 后整体非单调（T=0.7 > T=1.0）。不同 run 间 C0 有随机波动。核心结论不变：delta 始终=0，diversity 不是瓶颈。\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.75, \"sc_accuracy\": 0.75, \"delta_pp\": 0, \"multi_candidate_rate\": 0.433, \"discordant_total\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 1}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T16:47:11.985Z\"}, \"exp-012-gsm8k-pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T16:47:20.559Z\", \"updated_at\": \"2026-05-17T17:09:35.283Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 GSM8K (开放答案数学域) 30 题上 SICA vs SC。预期 C0<20%（14B 在 GSM8K 太强），验证 C0 作为 SICA 无效性预测指标。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_exp012_gsm8k.sh\", \"server\": \"westd-32608\", \"data_path\": \"data/gsm8k_200.json\", \"data_count\": 30, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct\", \"eval_data\": \"data/gsm8k_200.json\", \"gpu\": [\"cuda:0\"], \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp012_gsm8k/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp012_gsm8k/\"}, \"metrics\": {\"n\": 30, \"k\": 12, \"sica_accuracy\": 0.9667, \"sc_accuracy\": 0.9667, \"delta_pp\": 0, \"multi_candidate_rate\": 0.133, \"extraction_success_rate\": 0.147, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"GSM8K\", \"temperature\": 0.7}, \"conclusion\": \"negative\", \"notes\": \"GSM8K 30题：SICA=SC=96.67%，delta=0，C0=13.3%。开放答案数学域 baseline 极高（96.67%），几乎无 diversity（C0=13.3%），extraction_success_rate 仅 14.7%——数学域的 symbolic constraints 难以提取。支持 C0 作为 SICA 无效性预测指标。\", \"completed_at\": \"2026-05-17T17:09:35.283Z\"}, \"exp-021-oracle-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T16:36:04.545Z\", \"updated_at\": \"2026-05-17T16:48:21.295Z\", \"hypothesis\": \"If we replace self-extracted constraints with gold FOL annotations verified by Z3, Oracle-SICA should significantly outperform both SC and SICA, demonstrating that constraint quality is the bottleneck for SICA gains on formal logic tasks.\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"python scripts/run_exp021_oracle_folio.py\", \"server\": \"westd-32608\", \"data_path\": \"data/folio_full.json + results/sica_expanded_14b.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct (traces) + Z3 (oracle constraints)\", \"seed\": 42, \"checkpoint_path\": \"results/exp021_oracle_folio/exp021_results.json\", \"log_path\": \"results/exp021_oracle_folio/exp021_summary.json\", \"checkpoint_source\": \"results/sica_expanded_14b.json\", \"eval_data\": \"data/folio_full.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T16:45:52.280Z\", \"metrics\": {\"n\": 204, \"k\": 12, \"oracle_sica_accuracy\": 0.8824, \"sc_accuracy\": 0.7941, \"sica_self_accuracy\": 0.7941, \"oracle_vs_sc_delta_pp\": 8.82, \"oracle_vs_sica_delta_pp\": 8.82, \"mcnemar_p_oracle_vs_sc\": 6.15e-05, \"z3_gold_agreement\": 0.946, \"fol_parse_success\": 1, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\", \"constraint_source\": \"gold FOL annotations\"}, \"notes\": \"KEY RESULT. Oracle-SICA (gold FOL + Z3 consistency check + MAX-SAT) 88.24% vs SC 79.41% vs SICA(self-extracted) 79.41%, +8.82pp, McNemar p=6.15e-05 高度显著。Z3 solver 与 gold answer 一致率 94.6%（193/204），FOL parser 204/204 全部成功。SICA(self)=SC 确认 LLM 自提取约束在 formal logic 上无有效信号。结论：MAX-SAT 聚合机制本身有效——瓶颈在约束提取质量，不在聚合算法。这直接回答了 Reviewer 的核心 confound 质疑。\"}, \"temperature-ablation-t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:45:59.468Z\", \"updated_at\": \"2026-05-17T16:47:09.843Z\", \"hypothesis\": \"Temperature ablation T=0.5: 中温下 Qwen2.5-14B trace diversity 中等（C0 预期 30-45%），SICA-SC gap 预期≈0——验证即使 diversity 适中，constraint quality 仍为瓶颈\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_temperature_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T0.5_results.json\", \"log_path\": \"/tmp/temperature_ablation.log\"}, \"notes\": \"T=0.5 中温：C0=38.3%，SICA=SC=76.67%，delta=0，discordant=0。中等 diversity 下 SICA 仍完全等于 SC。\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.7667, \"sc_accuracy\": 0.7667, \"delta_pp\": 0, \"multi_candidate_rate\": 0.383, \"discordant_total\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.5}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T16:47:09.843Z\"}, \"temperature-ablation-t03\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:45:57.395Z\", \"updated_at\": \"2026-05-17T16:47:07.935Z\", \"hypothesis\": \"Temperature ablation T=0.3: 低温下 Qwen2.5-14B trace diversity 降低（C0 预期<30%），SICA-SC gap 预期≈0——验证 diversity 不足时 SICA 无操作空间，capability trap 的下界\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_temperature_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T0.3_results.json\", \"log_path\": \"/tmp/temperature_ablation.log\"}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.7333, \"sc_accuracy\": 0.7333, \"delta_pp\": 0, \"multi_candidate_rate\": 0.3, \"discordant_total\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.3}, \"conclusion\": \"negative\", \"notes\": \"T=0.3 低温：C0=30%（符合预期低于 T=0.7 的 53%），SICA=SC=73.33%，delta=0，discordant=0。低温降低 diversity 但 SICA 无任何改变——约束完全无判别力。\", \"completed_at\": \"2026-05-17T16:47:07.935Z\"}, \"exp-014-deepseek-r1-7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:52:10.748Z\", \"updated_at\": \"2026-05-17T13:43:42.275Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B（reasoning distill 模型）在 D012 上 SICA vs SC——预期 C0<5%（类似 QwQ-32B，reasoning model 的确定性链消灭多样性），作为第二个 reasoning model 数据点验证 capability trap\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp014_deepseek_r1_7b.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": 324400, \"log_path\": \"~/runs/symb_invariant_consensus/exp-014-deepseek-r1-7b.log\", \"submitted_at\": \"2026-05-17T11:52:19.117Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/\", \"data_count\": 60, \"model_name\": \"DeepSeek-R1-Distill-Qwen-7B\", \"seed\": 42, \"checkpoint_source\": \"HuggingFace deepseek-ai/DeepSeek-R1-Distill-Qwen-7B\", \"eval_data\": \"D012 (30PW+30FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp014_deepseek_r1_7b/exp014_results.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T13:34:23.083Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:34:24.985786+00:00\"}]}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.6833, \"sc_accuracy\": 0.7167, \"delta_pp\": -3.33, \"multi_candidate_rate\": 0.583, \"extraction_rate\": 0.839, \"answer_extraction_rate\": 0.939, \"truncated_traces\": 72, \"contradiction_rate\": 0.037, \"wall_time_min\": 100.3, \"mcnemar_p\": 0.4795, \"discordant_sica_wins\": 0, \"discordant_sc_wins\": 2, \"model\": \"DeepSeek-R1-Distill-Qwen-7B\", \"dataset\": \"D012\"}, \"conclusion\": \"negative\", \"notes\": \"假设预判错误：预期 C0<5%（类似 QwQ-32B reasoning model），实际 C0=58.3%。DeepSeek-R1-Distill-Qwen-7B 因 7B 容量不足以维持确定性推理链，表现为 instruction-scale model。SICA -3.3pp，两子域对称（FOLIO -3.3pp, PW -3.3pp）。重新定位为第四个 instruction-scale 模型验证 capability trap。\", \"completed_at\": \"2026-05-17T13:42:50.983Z\"}, \"exp-010-mistral-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:48:05.255Z\", \"updated_at\": \"2026-05-17T13:39:59.922Z\", \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 跨模型家族泛化（v3: 脚本内含 vLLM 清理+conda 环境，解决 v2 SIGTERM 问题）\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp010_mistral.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"298717\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral-v3.log\", \"submitted_at\": \"2026-05-17T07:56:55.973Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"data_count\": 60, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"huggingface:mistralai/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"ProofWriter-D5 + FOLIO (D012 split)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp010_mistral_v3/\", \"wall_clock_seconds\": 1506.4, \"gpu_hours\": 0.42}, \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"reproduce\": {\"finished_at\": \"2026-05-17T08:17:39.965Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T08:17:42.415004+00:00\"}]}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.4833, \"sc_accuracy\": 0.4833, \"delta_pp\": 0, \"multi_candidate_rate\": 0.5, \"extraction_rate\": 0.8819, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.0562, \"discordant_sica_wins\": 2, \"discordant_sc_wins\": 2, \"mcnemar_p\": 1, \"proofwriter_sica\": 0.4, \"proofwriter_sc\": 0.4, \"proofwriter_delta_pp\": 0, \"folio_sica\": 0.5667, \"folio_sc\": 0.5667, \"folio_delta_pp\": 0, \"truncated_traces\": 0, \"model\": \"Mistral-7B-Instruct-v0.3\", \"dataset\": \"D012\"}, \"conclusion\": \"negative\", \"notes\": \"Mistral-7B cross-family: SICA 48.33% = SC 48.33%, delta=0.00pp。Multi-candidate rate 50%（30/60 题非 unanimous），SICA 仅改变 4 题（6.67% flip rate）。模型太弱：SC baseline 48.33%（近随机），trace 缺乏质量但有多样性。Discordant 2:2 平局，McNemar p=1.0。支持 operating regime 有下界：模型必须足够强才能生成有意义的 diverse traces。PW 40%/40%, FOLIO 56.67%/56.67%。\", \"completed_at\": \"2026-05-17T08:22:02.386Z\"}, \"sica_expanded_14b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:12:00.374Z\", \"updated_at\": \"2026-05-17T13:26:43.835Z\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --pw-data data/proofwriter_full.json --folio-data data/folio_full.json --math-data data/empty.json --output results/sica_expanded_14b.json --save-intermediates\", \"server\": \"westd-32608\", \"data_path\": \"data/proofwriter_full.json (600 D5) + data/folio_full.json (204)\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"pid\": \"181491\", \"gpu\": [\"cuda:0\"], \"log_path\": \"~/runs/symb_invariant_consensus/sica_expanded_14b.log\", \"submitted_at\": \"2026-05-16T05:19:00.966Z\", \"backend\": \"nohup\", \"account\": \"root\", \"eta_hours\": 13.4, \"wall_clock_seconds\": 50368.9, \"gpu_hours\": 13.99}, \"reproduce\": {\"finished_at\": \"2026-05-16T19:18:29.155Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T19:18:29.888Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T19:18:30.703230+00:00\"}]}, \"metrics\": {\"sica_accuracy\": 0.765, \"sc_accuracy\": 0.762, \"sica_sc_gap_pp\": 0.3, \"n_problems\": 804, \"multi_candidate_rate\": 0.3818, \"folio_sica\": 0.794, \"folio_sc\": 0.794, \"folio_gap_pp\": 0, \"folio_n\": 204, \"proofwriter_sica\": 0.755, \"proofwriter_sc\": 0.752, \"proofwriter_gap_pp\": 0.3, \"proofwriter_n\": 600, \"extraction_rate\": 0.89, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.022, \"problems_with_contradictions\": 331, \"truncated_traces\": 0, \"wall_time_min\": 826}, \"notes\": \"实验完整完成 804/804 题并保存结果。EXIT_CODE=129 是 SIGHUP 伪信号（进程退出阶段收到），非真实失败。日志末尾打印 \\\"FULL_MVP_DONE\\\" 后才出现 exit code。D025 pivot 确认：SICA≈SC (+0.3pp, N=804)，D012 +3.3pp 是小样本噪声。FOLIO sub-claim dead (0pp)。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/sica_expanded_14b.json\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 N=804 (600PW+204FOLIO) 上 SICA 相比 SC 有统计显著优势（p<0.05）——full-scale validation of D012 preliminary +3.3pp signal\", \"parent\": \"sica_d012_14b\"}, \"exp-019-llama8b-strategyqa-200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:07:01.919Z\", \"updated_at\": \"2026-05-17T13:26:41.871Z\", \"hypothesis\": \"Powered test: SICA 在弱模型（LLaMA-3.1-8B）上的增益在 n=200 StrategyQA 题时达到统计显著（p<0.05）——验证 operating regime 假设（D031 + exp-011 directionally positive +6.67pp）\", \"parent\": \"exp-011-llama8b-v3\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T08:18:21.546Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp019_strategyqa_200.sh\\\"\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T09:10:18.592Z\", \"training_hours\": 0.87}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp019_strategyqa_200.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"302372\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-019-llama8b-strategyqa-200.log\", \"submitted_at\": \"2026-05-17T08:18:24.001Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp019_strategyqa_200/\", \"wall_clock_seconds\": 3450.0, \"gpu_hours\": 0.96}, \"pid\": \"302372\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-019-llama8b-strategyqa-200.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:10:21.404482+00:00\"}]}, \"metrics\": {\"n\": 200, \"k\": 12, \"sica_accuracy\": 0.74, \"sc_accuracy\": 0.72, \"delta_pp\": 2, \"multi_candidate_rate\": 0.41, \"mcnemar_p\": 0.424, \"bootstrap_ci_95\": [-1.5, 5.5], \"bootstrap_p_delta_le_0\": 0.12, \"discordant_sica_wins\": 9, \"discordant_sc_wins\": 5, \"discordant_total\": 14, \"discordant_rate\": 0.07, \"sc_unanimous_rate\": 0.545, \"model\": \"LLaMA-3.1-8B-Instruct\", \"dataset\": \"StrategyQA\", \"wall_time_min\": 52}, \"conclusion\": \"negative\", \"notes\": \"StrategyQA 200题 powered test: SICA 74% vs SC 72%, +2.00pp, McNemar p=0.424, bootstrap CI [-1.5, +5.5] 跨零。统计不显著。exp-011 的 +6.67pp 在扩大样本后缩水 70%——小样本噪声。关键发现：(1) LLaMA-8B 在 StrategyQA 上 SC=72%，高于预期的 sweet spot (55-65%)，(2) 仅 14/200 (7%) discordant pairs，54.5% 全票一致，(3) SICA 仅充当 tiebreaker（9 wins 中 6 个是平票）。StrategyQA 不在 operating regime sweet spot 内。exp-020 FOLIO (SC≈60%) 是真正的 definitive test。\", \"completed_at\": \"2026-05-17T09:15:53.996Z\"}, \"exp-018-arc-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:13:27.054Z\", \"updated_at\": \"2026-05-17T13:26:39.502Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 ARC-Challenge (科学多选, ABCD) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（v2: build_generator bug 已修复）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T06:19:18.377Z\", \"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_exp018_arc.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T06:39:42.063Z\", \"training_hours\": 0.34}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_exp018_arc.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"289541\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-018-arc-v2.log\", \"submitted_at\": \"2026-05-17T06:19:19.350Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1433.8, \"gpu_hours\": 0.4}, \"pid\": \"289541\", \"log_path\": \"/root/symb_invariant_consensus/results/exp018_arc/exp018_results.json\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T06:39:44.088518+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.95, \"sc_accuracy\": 0.9667, \"delta_pp\": -1.67, \"multi_candidate_rate\": 0.05, \"extraction_rate\": 1, \"contradiction_detected\": 3, \"discordant_sica_wins\": 0, \"discordant_sc_wins\": 1, \"dataset\": \"ARC-Challenge\", \"model\": \"Qwen2.5-14B-Instruct\"}, \"notes\": \"ARC-Challenge cross-domain: SICA 95.00% vs SC 96.67%, gap=-1.67pp. SICA 略逊于 SC。模型在 ARC 上 baseline 极高(96.67%)，接近天花板——高准确率区间多样性低，SICA 无操作空间。与 StrategyQA (+3.33pp n.s.) 对比：简单任务（高 baseline）SICA 无效或有害，中等难度任务有微弱正向趋势但不显著。整体支持 capability trap：模型能力越强/任务越简单 → SC 已近最优 → SICA 无增量。\", \"checkpoint_path\": \"N/A (evaluation experiment)\", \"completed_at\": \"2026-05-17T06:43:13.130Z\"}, \"exp-009-overhead-analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:51:43.293Z\", \"updated_at\": \"2026-05-17T12:01:08.521Z\", \"hypothesis\": \"SICA pipeline 的 wall-time overhead breakdown: trace generation vs constraint extraction vs MaxSAT solving 各占多少——量化 SICA 相对 SC 的额外计算成本\", \"metrics\": {\"n\": 804, \"mean_total_wall_s\": 61.6, \"mean_trace_gen_s\": 31.6, \"trace_gen_pct\": 51.3, \"mean_extract_s\": 29, \"extract_pct\": 47, \"mean_dedup_s\": 1, \"dedup_pct\": 1.6, \"mean_maxsat_s\": 0.003, \"maxsat_pct\": 0.005, \"sica_overhead_s\": 30, \"sica_overhead_pct\": 48.7, \"pw_overhead_pct\": 51.3, \"folio_overhead_pct\": 38.6, \"p50_overhead_pct\": 48.9, \"p90_overhead_pct\": 57.6}, \"conclusion\": \"success\", \"notes\": \"SICA overhead 分析 (804题)：总时间 61.6s/题，其中 trace 生成 31.6s (51.3%)，约束提取 29.0s (47.0%)，去重 1.0s (1.6%)，MaxSAT 0.003s (≈0%)。SICA vs SC 多花 30.0s/题 (+48.7%)，开销几乎全部来自 constraint extraction LLM 调用。MaxSAT 求解可忽略。论文 insight：SICA 的计算瓶颈不在 formal reasoning (SAT) 而在 LLM extraction，且 extraction 产出的约束缺乏判别力——高成本低回报。\", \"spec\": {\"command\": \"CPU-only analysis of exp-001 timing data\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/results/\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42}, \"checkpoint_path\": \"N/A (CPU-only analysis)\", \"log_path\": \"N/A (CPU-only analysis)\", \"completed_at\": \"2026-05-17T12:01:08.521Z\"}, \"exp-020-llama8b-folio-204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:12:49.897Z\", \"updated_at\": \"2026-05-17T11:50:57.467Z\", \"hypothesis\": \"Powered FOLIO test: SICA 在弱模型（LLaMA-3.1-8B）上 FOLIO 全量 204 题是否达到统计显著——FOLIO 在 exp-011 中信号最强（+10pp, bootstrap p≈0.04），n=204 几乎必然显著。保险实验：若 StrategyQA discordant rate 低导致 underpowered。\", \"parent\": \"exp-011-llama8b-v3\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp020_folio_200.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"309318\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-020-llama8b-folio-204.log\", \"submitted_at\": \"2026-05-17T09:12:58.789Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_204.jsonl\", \"data_count\": 204, \"model_name\": \"meta-llama/Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"N/A (inference-only, no checkpoint)\", \"eval_data\": \"FOLIO full dataset 204 problems\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp020_folio_200/\", \"wall_clock_seconds\": 9478.7, \"gpu_hours\": 2.63}, \"reproduce\": {\"finished_at\": \"2026-05-17T11:27:04.546Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:27:06.717657+00:00\"}]}, \"metrics\": {\"n\": 204, \"k\": 12, \"sica_accuracy\": 0.608, \"sc_accuracy\": 0.632, \"delta_pp\": -2.45, \"mcnemar_p\": 0.2668, \"bootstrap_ci_95\": [-5.88, 0.98], \"bootstrap_p_sica_ge_sc\": 0.1, \"discordant_sica_wins\": 4, \"discordant_sc_wins\": 9, \"discordant_total\": 13, \"discordant_rate\": 0.064, \"multi_candidate_rate\": 0.618, \"extraction_rate\": 0.942, \"answer_extraction_rate\": 0.951, \"contradiction_rate\": 0.062, \"both_wrong\": 71, \"model\": \"LLaMA-3.1-8B-Instruct\", \"dataset\": \"FOLIO-204\", \"wall_time_min\": 131.7}, \"conclusion\": \"negative\", \"notes\": \"DEFINITIVE NEGATIVE。LLaMA-8B FOLIO 204题：SICA 60.8% vs SC 63.2%, delta=-2.45pp, McNemar p=0.2668, CI [-5.88, +0.98]。Discordant 4:9 SICA 输多赢少。exp-011 FOLIO +10pp 在 n=204 完全反转为 -2.45pp——确认为 Type I error (n=30 随机波动)。C0=61.8% 高（SICA 有操作空间），但约束改票时反而引入更多错误(9 SC wins vs 4 SICA wins)。Sweet spot hypothesis 被否定。SICA≤SC everywhere 确认。\", \"completed_at\": \"2026-05-17T11:50:57.467Z\"}, \"pilot-contrastive-prompt\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:18:22.559Z\", \"updated_at\": \"2026-05-17T08:02:40.938Z\", \"hypothesis\": \"Contrastive Prompt Extraction: 将 prompt 改为\\\"列出支持答案X/反对答案Y的证据\\\"能否将 discriminative ratio 从 37.2% 提升至 >70%，并使 SICA(contrastive) > SC ≥3pp——验证 answer-conditioned 约束是否解决 SICA 机制 vacuous 问题\", \"parent\": \"pilot-constraint-filtering\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T06:42:48.028Z\", \"command\": \"cd /root/symb_invariant_consensus && python scripts/pilot_contrastive_constraints.py\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T06:43:15.557Z\", \"training_hours\": 0.01}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python scripts/pilot_contrastive_constraints.py\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-contrastive-prompt.log\", \"submitted_at\": \"2026-05-17T06:42:49.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 26.8, \"gpu_hours\": 0.01}, \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-contrastive-prompt.log\", \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T06:43:16.479Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T06:43:18.090519+00:00\"}]}, \"notes\": \"脚本已验证可用（run_pilot_contrastive_v2.sh + pilot_contrastive_constraints.py）。修复方案：submit 时用 bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && bash /root/symb_invariant_consensus/scripts/run_pilot_contrastive_v2.sh\\\" 包裹。当前 GPU 被 exp-010-mistral-v3 占用（vLLM 87880MiB），等其完成后提交。\"}, \"exp-011-llama8b-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:15:02.161Z\", \"updated_at\": \"2026-05-17T07:59:02.260Z\", \"hypothesis\": \"Cross-family validation: LLaMA-3.1-8B-Instruct 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 非 Qwen-specific（v3: 模型 shard 已修复，GPU 空闲后提交）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T06:45:47.789Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp011_llama8b.sh\\\"\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T07:55:14.227Z\", \"training_hours\": 1.16}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp011_llama8b.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"292780\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v3.log\", \"submitted_at\": \"2026-05-17T06:45:49.636Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4392.6, \"gpu_hours\": 1.22}, \"pid\": \"292780\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v3.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T07:55:16.092007+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.6667, \"sc_accuracy\": 0.6, \"delta_pp\": 6.67, \"multi_candidate_rate\": 0.6167, \"extraction_rate\": 0.8556, \"answer_extraction_rate\": 0.8958, \"contradiction_rate\": 0.0527, \"problems_with_contradictions\": 43, \"truncated_traces\": 44, \"discordant_sica_wins\": 5, \"discordant_sc_wins\": 1, \"mcnemar_p\": 0.2188, \"proofwriter_sica\": 0.6333, \"proofwriter_sc\": 0.6, \"proofwriter_delta_pp\": 3.33, \"folio_sica\": 0.7, \"folio_sc\": 0.6, \"folio_delta_pp\": 10, \"model\": \"LLaMA-3.1-8B-Instruct\", \"dataset\": \"D012\", \"wall_time_min\": 66.4}, \"notes\": \"LLaMA-3.1-8B cross-family: SICA 66.7% vs SC 60.0%, +6.67pp (最大增益)。Discordant 5:1 强烈倾向 SICA。FOLIO +10pp, PW +3.33pp。McNemar p=0.22（n=60 受限）。Multi-candidate rate 61.7%（vs Qwen-14B 46%）——弱模型更多样→SICA 有更大操作空间。44 条 truncated traces（max-tokens 可能偏短），但仍有效。关键：SC baseline 60%（远低于 Qwen-14B 的 76%），验证 capability trap 的正面——模型弱时 SICA 有用。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp011_llama8b/exp011_results.json\", \"completed_at\": \"2026-05-17T07:59:02.260Z\"}, \"exp-010-mistral-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:26:42.201Z\", \"updated_at\": \"2026-05-17T06:19:34.268Z\", \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 跨模型家族泛化（v2: 修复 max-model-len=8192 防 400 循环）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T05:51:38.846Z\", \"command\": \"pkill -f \\\"vllm.entrypoints\\\" 2>/dev/null; sleep 3; cd /root/symb_invariant_consensus && bash scripts/run_exp010_mistral.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T05:51:53.254Z\", \"training_hours\": 0.0}, \"spec\": {\"command\": \"pkill -f \\\"vllm.entrypoints\\\" 2>/dev/null; sleep 3; cd /root/symb_invariant_consensus && bash scripts/run_exp010_mistral.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral-v2.log\", \"submitted_at\": \"2026-05-17T05:51:40.607Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13.6, \"gpu_hours\": 0.0}, \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral-v2.log\", \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T05:51:54.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T05:51:55.875957+00:00\"}]}, \"notes\": \"SIGTERM (exit 143) 在提交后 ~15s。根因：compound command 中 pkill -f \\\"vllm.entrypoints\\\" 可能误杀 tmux 父进程链。Director 已明确禁止 pkill 和 bash 脚本写在同一行。需要 v3：先手动清理 vLLM，再独立提交脚本。\"}, \"pilot-constraint-filtering\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T04:47:05.171Z\", \"updated_at\": \"2026-05-17T06:11:36.503Z\", \"hypothesis\": \"Constraint Consistency Filtering: 只保留在≥T条traces中重复出现的约束能否提升SICA accuracy超过SC——验证约束质量过滤是否解决capability trap\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T04:47:13.762Z\", \"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_pilot_constraint_filtering.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T05:28:15.355Z\", \"training_hours\": 0.68}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_pilot_constraint_filtering.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"282213\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-constraint-filtering.log\", \"submitted_at\": \"2026-05-17T04:47:15.480Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 5013.4, \"gpu_hours\": 1.39}, \"pid\": \"282213\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-constraint-filtering.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T05:28:16.989563+00:00\"}]}, \"conclusion\": \"negative\", \"notes\": \"NEGATIVE confirmed. T=1/2/3 结果完全一致(+2.33pp=1题翻转), T≥5 SICA退化为SC。Discriminative analysis: unique constraints 中 11.5% 是 discriminative (by count), 37.2% (by weight)。但有效 flip 率仅 4/23=17.4%。根本原因：提取的约束是 domain facts (kind_charlie==True, Implies(...)) — 无论答案是什么，中间推理步骤大部分共通。约束系统未提取答案级别判别谓词。Constraint filtering 天花板极低，不是 rescue path。\", \"checkpoint_path\": \"N/A (analysis experiment, no checkpoint)\", \"completed_at\": \"2026-05-17T06:10:48.874Z\", \"metrics\": {\"n\": 43, \"thresholds_tested\": [1, 2, 3, 5, 7], \"best_gap_pp\": 2.33, \"best_T\": 1, \"sica_T1\": 0.7674, \"sc\": 0.7442, \"T5_gap\": 0, \"T7_gap\": 0, \"discriminative_ratio_count\": 0.115, \"discriminative_ratio_weight\": 0.372, \"effective_flip_rate\": 0.174, \"multi_answer_problems\": 23, \"unanimous_problems\": 20, \"problems_disc_favors_different\": 4}}, \"exp-018-arc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:19:51.591Z\", \"updated_at\": \"2026-05-17T05:31:46.070Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 ARC-Challenge (科学多选, ABCD) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（多选题型）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T05:30:39.347Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp018_arc.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T05:30:48.403Z\", \"training_hours\": 0.0}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp018_arc.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"285496\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-018-arc.log\", \"submitted_at\": \"2026-05-17T05:30:41.118Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 8.2, \"gpu_hours\": 0.0}, \"pid\": \"285496\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-018-arc.log\", \"failure_reason\": \"Traceback → al_arc.py\\\", line 244, in &lt;module> main() File \\\"/root/symb_invariant_consensus/scripts/eval_arc.py\\\", line 142, in main generator = build_generator(args) ^^^^^^^^^^^^^^^ NameError: name 'build_generator' is not defined. Did you mean: 'build_extractor'?\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T05:30:49.360Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T05:30:50.922842+00:00\"}]}, \"notes\": \"NameError: name 'build_generator' is not defined in eval_arc.py:142. 代码bug——函数未定义/未导入。Worker 诊断修复中。\"}, \"exp-017-strategyqa-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T04:17:54.931Z\", \"updated_at\": \"2026-05-17T05:29:12.136Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 StrategyQA (常识推理, Yes/No) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（v3: 修复 True/False→Yes/No 提取 bug）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T04:18:02.638Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T04:26:23.412Z\", \"training_hours\": 0.14}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"278827\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v3.log\", \"submitted_at\": \"2026-05-17T04:18:04.451Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4267.7, \"gpu_hours\": 1.19}, \"pid\": \"278827\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v3.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T04:26:25.041303+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.5667, \"sc_accuracy\": 0.5333, \"delta_pp\": 3.33, \"mcnemar_chi2\": 0.5, \"mcnemar_p\": \"n.s.\", \"bootstrap_ci_95\": [0, 8.33], \"bootstrap_p_delta_le_0\": 0.1346, \"multi_candidate_rate\": 0.1, \"contradiction_detected\": 5, \"extraction_rate_problem\": 1, \"extraction_rate_trace\": 0.704, \"discordant_sica_wins\": 2, \"discordant_sc_wins\": 0}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp017_strategyqa/exp017_results.json\", \"notes\": \"StrategyQA跨域验证: SICA 56.67% vs SC 53.33%, +3.33pp n.s. (p=0.13), 支持capability trap跨任务泛化; v3修复提取bug确认成功(100%问题级提取率); 2个discordant pairs均SICA胜出\", \"completed_at\": \"2026-05-17T05:29:12.136Z\"}, \"exp-017-strategyqa-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:50:55.005Z\", \"updated_at\": \"2026-05-17T04:27:27.997Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 StrategyQA (常识推理, Yes/No) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（非逻辑/数学域）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:51:02.300Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T04:01:13.600Z\", \"training_hours\": 0.17}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"274312\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v2.log\", \"submitted_at\": \"2026-05-17T03:51:04.002Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2184.0, \"gpu_hours\": 0.61}, \"pid\": \"274312\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T04:01:15.665453+00:00\"}]}, \"conclusion\": \"failed\", \"failure_reason\": \"答案提取bug: 73.3% (44/60) answer=\\\"\\\"。Pipeline输出True/False但extractor只认Yes/No。数据无效，需修复后重跑。\", \"completed_at\": \"2026-05-17T04:27:27.997Z\"}, \"exp-017-strategyqa\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:19:50.628Z\", \"updated_at\": \"2026-05-17T03:50:54.370Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 StrategyQA (常识推理, Yes/No) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（非逻辑/数学域）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:46:30.089Z\", \"command\": \"pkill -f vllm 2>/dev/null || true; sleep 2; bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T03:47:02.948Z\", \"training_hours\": 0.01}, \"spec\": {\"command\": \"pkill -f vllm 2>/dev/null || true; sleep 2; bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa.log\", \"submitted_at\": \"2026-05-17T03:46:31.684Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 32.2, \"gpu_hours\": 0.01}, \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa.log\", \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T03:47:03.842Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:47:05.693732+00:00\"}]}}, \"exp-010-mistral\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T01:04:36.900Z\", \"updated_at\": \"2026-05-17T03:37:29.439Z\", \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 D012 数据集上是否复现 SICA≈SC pattern——验证 capability trap 跨模型家族泛化\", \"parent\": \"sica_expanded_14b\", \"notes\": \"模型已确认完整下载：3 shards (4.95+5.00+4.55GB) + consolidated.safetensors (14.5GB)。排在 exp-018 之后启动。需要 Worker 准备启动脚本（参照 exp-011 模式）。\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:22:52.734Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp010_mistral.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T03:37:29.116Z\", \"training_hours\": 0.24}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp010_mistral.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"270100\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral.log\", \"submitted_at\": \"2026-05-17T03:22:54.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 875.2, \"gpu_hours\": 0.24}, \"pid\": \"270100\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral.log\", \"conclusion\": \"failed\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-17T03:37:29.439Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:37:31.206441+00:00\"}]}}, \"exp-011-llama8b-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:19:49.625Z\", \"updated_at\": \"2026-05-17T03:24:54.392Z\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:19:59.814Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T03:22:16.279Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"269123\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v2.log\", \"submitted_at\": \"2026-05-17T03:20:01.559Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 135.6, \"gpu_hours\": 0.04}, \"pid\": \"269123\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v2.log\", \"hypothesis\": \"Cross-family validation: LLaMA-3.1-8B-Instruct 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 非 Qwen-specific (v2: 修复 GPU OOM，kill 旧 vLLM 后重跑)\", \"parent\": \"sica_expanded_14b\", \"failure_reason\": \"模型权重损坏: model-00002-of-00004.safetensors 下载不完整 (3.7G vs 预期 ~4.9G)，safetensors_rust.SafetensorError\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T03:22:17.134Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:22:18.620317+00:00\"}]}}, \"sica_temp_diversity\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:14:34.555Z\", \"updated_at\": \"2026-05-17T03:21:14.807Z\", \"spec\": {\"command\": \"python3 diagnose_diversity.py\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/math500_subset.json\", \"data_count\": 5, \"model_name\": \"QwQ-32B\", \"seed\": 42, \"method\": \"SICA-diagnostic\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/symb_invariant_consensus/results/diversity_diagnosis.json\"}, \"hypothesis\": \"不同 temperature (0.7/0.9/1.0) 下 QwQ-32B 是否产生足够的 trace 分歧以触发 MAX-SAT 矛盾检测\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T12:14:56.903Z\", \"metrics\": {\"temperatures_tested\": [0.7, 0.9, 1], \"problems_tested\": 3, \"problems_with_divergence\": 0, \"finding\": \"QwQ-32B produces zero answer divergence at all temperatures on MATH L4-5. Reasoning model's deterministic chain dominates sampling randomness.\", \"max_tokens_issue\": \"4096 tokens insufficient for some L5 problems (truncation)\", \"recommendation\": \"Use AIME 2024 (harder, ~79.5% acc) or non-reasoning model for trace diversity\"}, \"parent\": \"sica_smoke_5q\"}, \"sica_d012_14b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:02:41.309Z\", \"updated_at\": \"2026-05-17T03:21:14.256Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=0 python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --math-data /tmp/empty_math.json --pw-data data/proofwriter_30.json --folio-data data/folio_30.json --output results/sica_d012_14b.json --save-intermediates 2>&1 | tee /tmp/sica_d012_14b.log\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"177178\", \"log_path\": \"~/runs/symb_invariant_consensus/sica_d012_14b.log\", \"submitted_at\": \"2026-05-16T04:05:23.888Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 3809.2, \"gpu_hours\": 1.06}, \"reproduce\": {\"finished_at\": \"2026-05-16T05:04:49.668Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T05:04:50.574652+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"sica_accuracy\": 0.7333, \"sc_accuracy\": 0.7, \"sica_sc_gap_pp\": 3.3, \"c0_multi_candidate_rate\": 0.5333, \"c1_extraction_rate\": 1, \"c2_contradiction_problems\": 34, \"c3_gap_pp\": 3.3, \"bootstrap_p\": 0.2261, \"proofwriter_sica\": 0.6667, \"proofwriter_sc\": 0.6667, \"folio_sica\": 0.8, \"folio_sc\": 0.7333, \"total_constraints_raw\": 5849, \"total_constraints_unique\": 1735, \"maxsat_exclusion_rate\": 0.0259, \"wall_time_min\": 58.3, \"d012_verdict\": \"ALL_PASS\"}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/sica_d012_14b.json\", \"completed_at\": \"2026-05-16T05:08:53.052Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 D012 (30PW+30FOLIO) 上 SICA pipeline 端到端有效：C0(多候选率≥20%) + C1(提取率≥80%) + C2(矛盾率≥10%) + C3(SICA>SC) 四项 sanity check 全通过\", \"parent\": \"sica_d016_c0_precheck\"}, \"sica_k_sensitivity_14b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:12:03.025Z\", \"updated_at\": \"2026-05-17T03:19:48.625Z\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_k_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"237939\", \"log_path\": \"~/runs/symb_invariant_consensus/sica_k_sensitivity_14b.log\", \"submitted_at\": \"2026-05-16T20:00:54Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"k_values\": [6, 8, 11, 12, 16, 20], \"eta_hours\": 5.9, \"checkpoint_source\": \"Qwen2.5-14B-Instruct (base, no fine-tuning)\", \"eval_data\": \"D012 60 problems (PW30+FOLIO30)\", \"wall_clock_seconds\": 22151.7, \"gpu_hours\": 6.15}, \"hypothesis\": \"K-ablation: K={6,8,11,12,16,20} 对 SICA 效果的影响。K=11(奇数)无平票，若 gap=0 则证明 SICA 仅靠 tiebreak 生效\", \"parent\": \"sica_expanded_14b\", \"reproduce\": {\"finished_at\": \"2026-05-17T02:10:05.417Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T02:10:05.719Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T02:10:07.161307+00:00\"}]}, \"metrics\": {\"K6_sica\": 0.733, \"K6_sc\": 0.733, \"K6_gap_pp\": 0, \"K8_sica\": 0.733, \"K8_sc\": 0.75, \"K8_gap_pp\": -1.7, \"K11_sica\": 0.733, \"K11_sc\": 0.733, \"K11_gap_pp\": 0, \"K12_sica\": 0.7, \"K12_sc\": 0.75, \"K12_gap_pp\": -5, \"K16_sica\": 0.717, \"K16_sc\": 0.75, \"K16_gap_pp\": -3.3, \"K20_sica\": 0.7, \"K20_sc\": 0.733, \"K20_gap_pp\": -3.3, \"all_K_sica_leq_sc\": true, \"larger_K_degrades_sica\": true}, \"notes\": \"K-ablation 实际完成（EXIT_CODE=129 为 SIGHUP 假失败，同 sica_expanded_14b 模式）。结果：SICA ≤ SC for all K。K=11(奇数)验证 tiebreak 无贡献(gap=0)。K=12/16/20 SICA 退化 -3~5pp，表明更多 traces 引入更多低质量约束反而有害。直接强化 C1 (mechanism vacuous)。Artifact: art_20260517_2c1577。\"}, \"exp-011-llama8b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T01:00:32.450Z\", \"updated_at\": \"2026-05-17T03:00:35.641Z\", \"hypothesis\": \"Cross-family validation: LLaMA-3.1-8B-Instruct 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 非 Qwen-specific\", \"parent\": \"sica_expanded_14b\", \"notes\": \"Prep done by worker_prep_exp-011-llama8b_20260516T204635. Model: LLaMA-3.1-8B-Instruct (14GB, 4 shards). Script: /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh. Dataset: D012 (30 PW + 30 FOLIO = 60 题). 预估 ~25-30GB GPU, ~1-1.5h runtime. 等 sica_k_sensitivity_14b 完成后启动。\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T02:56:05.600Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T02:58:40.441Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"266576\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b.log\", \"submitted_at\": \"2026-05-17T02:56:07.282Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 154.1, \"gpu_hours\": 0.04}, \"pid\": \"266576\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T02:58:41.363Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T02:58:43.037174+00:00\"}]}}, \"exp-016-weighted-sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T01:01:51.841Z\", \"updated_at\": \"2026-05-17T01:02:16.162Z\", \"hypothesis\": \"加权投票变体(inverse-length/length-weighted/constraint-count)是否比 uniform SC 有统计显著优势——验证简单启发式能否替代 SICA 或超越 SC\", \"parent\": \"sica_expanded_14b\", \"conclusion\": \"success\", \"metrics\": {\"sica_accuracy\": 0.7649, \"sc_uniform_accuracy\": 0.7624, \"inv_length_accuracy\": 0.7674, \"length_weighted_accuracy\": 0.7525, \"constraint_count_accuracy\": 0.7525, \"inv_length_vs_sc_p\": 0.453, \"length_vs_sc_p\": 0.153, \"inv_length_vs_sica_p\": 0.864, \"length_vs_sica_p\": 0.066, \"n_problems\": 804, \"all_nonsignificant\": true}, \"notes\": \"exp-016 weighted SC baselines 完成。804题上所有加权变体 vs SC/SICA 均不显著(p>0.05)。Length-weighting 反而 -1pp（长 trace 略不可靠），inv-length +0.5pp 但非显著。结论：简单启发式加权不能替代也不能超越 uniform voting。支持 C1 (mechanism vacuous) — 问题不在聚合方式，而在约束质量本身。Artifacts: art_20260516_c7cc07 (report), art_20260516_7eef43 (data).\", \"spec\": {\"checkpoint_path\": \"N/A (analysis on existing traces)\", \"log_path\": \"N/A\", \"command\": \"python scripts/weighted_sc_baseline.py\", \"server\": \"westd-32608\", \"data_path\": \"exp-001 traces (804 problems)\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct (reuse)\", \"seed\": \"N/A\"}, \"completed_at\": \"2026-05-17T01:02:16.162Z\"}, \"exp-005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T20:52:36.217Z\", \"updated_at\": \"2026-05-16T20:53:22.616Z\", \"hypothesis\": \"QwQ-32B 作为 reasoning model 展示 SICA 的 operating regime boundary: 模型过强→diversity 消失→SICA≡SC\", \"parent\": \"sica_aime30_v3\", \"spec\": {\"command\": \"CPU-only data analysis: aggregate QwQ-32B negative results\", \"server\": \"westd-32608\", \"data_path\": \"results/aime30_v2.json + results/proofwriter_30_v2.json + results/folio_livetest.json + results/diversity_diagnosis.json\", \"data_count\": 46, \"model_name\": \"QwQ-32B (analysis target) vs Qwen2.5-14B-Instruct (comparison)\", \"seed\": \"N/A\", \"checkpoint_source\": \"N/A (CPU-only analysis, no model checkpoint)\", \"eval_data\": \"Aggregated outputs from sica_aime30_v3 (22q), sica_proofwriter30_v2 (17q), sica_folio30 (2q), sica_temp_diversity (5q)\"}, \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"artifacts/exp-005/data/operating_regime_data.json + artifacts/exp-005/report/operating_regime_report.md\", \"metrics\": {\"qwq_aggregate_c0_nominal_pct\": 10.3, \"qwq_aggregate_c0_effective_pct\": 2.6, \"qwen14b_c0_pct\": 46, \"diversity_ratio_effective\": 17.7, \"aime_delta_pp\": 0, \"proofwriter_delta_pp\": -5.9, \"aime_n\": 22, \"proofwriter_n\": 17, \"temp_diversity_n\": 5, \"folio_n\": 2, \"total_problems\": 46, \"c0_threshold\": 20, \"qwq_below_threshold\": true}, \"conclusion\": \"negative\", \"notes\": \"exp-005 Operating Regime Analysis 完成。QwQ-32B 综合 46 题数据：effective C0=2.6%，远低于 20% 阈值。数学域 SICA≡SC (Δ=0pp, AIME 22题)，逻辑域 SICA&lt;SC (Δ=−5.9pp, PW 17题)。对比 Qwen2.5-14B C0=46% (17.7x)。直接支持 paper Claim 2 (operating regime boundary)。Artifacts: art_20260516_bf444f (data), art_20260516_d6966d (report)。\", \"completed_at\": \"2026-05-16T20:53:22.616Z\"}, \"sica_folio30\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:08:43.460Z\", \"updated_at\": \"2026-05-16T04:42:53.530Z\", \"hypothesis\": \"逻辑域（FOLIO）上 SICA 能否利用 FOL 标注检测跨路径矛盾并超越 SC@K=12——FOLIO 有天然 FOL 标注，是 SICA 约束提取的理想场景\", \"parent\": \"sica_aime30_v3\", \"spec\": {\"hypothesis\": \"FOLIO 逻辑域上 SICA 能否利用 FOL 标注检测跨路径矛盾并超越 SC@K=12\", \"dataset\": \"FOLIO (yale-nlp/FOLIO validation subset)\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_subset.json\", \"data_count\": 30, \"label_distribution\": {\"True\": 10, \"False\": 10, \"Unknown\": 10}, \"has_fol_annotations\": true, \"model_name\": \"QwQ-32B\", \"server\": \"westd-32608\", \"command\": \"python eval_folio.py --n-problems 30 --k 12 --temperature 0.7 --max-tokens 12288 --seed 42 --save-intermediates --output results/folio_eval.json\", \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 12288, \"seed\": 42, \"eval_script\": \"/root/symb_invariant_consensus/eval_folio.py\", \"dry_run_passed\": true, \"live_test_passed\": true, \"live_test_result\": \"2/2 correct (SICA=100%, SC=100%), pipeline all stages functional\"}, \"notes\": \"废弃：QwQ-32B spec（max_tokens=12288），已被 sica_d012_14b（Qwen2.5-14B-Instruct 全量 D012 评估）覆盖。QwQ-32B 全域 C0 FAIL (3.6%)，模型已 pivot。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T04:42:50.715Z\"}, \"sica_d016_c0_precheck\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:00:14.192Z\", \"updated_at\": \"2026-05-16T04:01:11.163Z\", \"hypothesis\": \"D016 模型 pivot C0 预检：Qwen2.5-14B-Instruct 在逻辑域是否产生足够 trace 多样性（多候选率 ≥20%）\", \"parent\": \"sica_proofwriter30_v2\", \"spec\": {\"command\": \"python sica_pipeline.py --data folio_subset.json+proofwriter_subset.json --K 6 --T 0.7 --max-tokens 4096 --model Qwen2.5-14B-Instruct\", \"server\": \"westd-32608\", \"data_path\": \"data/folio_subset.json (10q) + data/proofwriter_subset.json (16q)\", \"data_count\": 26, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"model_path\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"hyperparams\": {\"K\": 6, \"T\": 0.7, \"max_tokens\": 4096, \"max_model_len\": 8192}, \"checkpoint_source\": \"N/A (inference-only, no checkpoint)\", \"eval_data\": \"FOLIO-10 + ProofWriter-16 (C0 precheck subset)\"}, \"metrics\": {\"multi_candidate_rate_combined\": 0.46, \"multi_candidate_rate_folio\": 0.4, \"multi_candidate_rate_proofwriter\": 0.5, \"sc_accuracy_combined\": 0.73, \"sc_accuracy_folio\": 0.8, \"sc_accuracy_proofwriter\": 0.69, \"n_problems\": 26, \"n_folio\": 10, \"n_proofwriter\": 16, \"K\": 6, \"T\": 0.7, \"total_time_s\": 280, \"c0_gate\": \"PASS (46% >= 20%)\", \"model\": \"Qwen2.5-14B-Instruct\", \"vllm_gpu_mem_gib\": 27.6, \"smoke_test\": \"2 problems end-to-end OK, constraints 21-26 per problem\"}, \"conclusion\": \"success\", \"notes\": \"C0 PASS: Qwen2.5-14B-Instruct 多候选率 46% (FOLIO 40%, ProofWriter 50%)，远超 20% 阈值。对比 QwQ-32B 全域 3.6%，提升 12.8x。SC accuracy 73% (FOLIO 80%, PW 69%)。Smoke test 2题 SICA pipeline 端到端通过。vLLM PID 174291, 27.6 GiB, max-model-len=8192。Report: art_20260516_e2774d。\", \"checkpoint_path\": \"N/A (inference-only precheck, no checkpoint)\", \"log_path\": \"artifacts/_project/report/d016_model_pivot_report.md (art_20260516_e2774d)\", \"completed_at\": \"2026-05-16T04:01:11.163Z\"}, \"sica_proofwriter30_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:19:01.325Z\", \"updated_at\": \"2026-05-16T01:38:43.002Z\", \"hypothesis\": \"逻辑域（ProofWriter D5）上 SICA 能否检测跨路径 FOL 约束矛盾并超越 SC@K=12（v2: max_tokens=12288 修复）\", \"parent\": \"sica_proofwriter30\", \"spec\": {\"command\": \"python eval_proofwriter.py --n-problems 30 --k 12 --max-tokens 12288 --seed 42 --save-intermediates --output results/proofwriter_30_v2.json\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"155077\", \"log_path\": \"/root/runs/symb_invariant_consensus/proofwriter30_v2.log\", \"submitted_at\": \"2026-05-15T22:19:16.529Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_subset.json\", \"data_count\": 30, \"seed\": 42, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 12288, \"domain\": \"logic\", \"extraction_prompt\": \"LOGIC_EXTRACTION_PROMPT\", \"z3_timeout_s\": 60, \"checkpoint_source\": \"N/A (new SICA logic domain experiment, retry of sica_proofwriter30 with fixed max_tokens)\", \"eval_data\": \"ProofWriter D5 30 problems (T:10 F:10 U:10)\", \"wall_clock_seconds\": 11503.9, \"gpu_hours\": 3.2}, \"notes\": \"16/30 killed (Director 指令)。D012 四项全 FAIL。MaxSAT 根因诊断结论：三层问题叠加——(1) 约束提取失败 54.4%，QwQ-32B 收到 extraction prompt 后重新推理而非输出 JSON，3/4 多候选题提取为零；(2) 一致投票=一致约束，14/17 题 12/12 同一答案，约束天然不矛盾（正确行为非 bug）；(3) 评分偏差，唯一 SICA≠SC 的题 498_Q8，SICA 给少数派 38 分 > 多数派 27 分，因提取失败非随机。MaxSAT 求解器本身无 bug（注入测试 6/6 通过）。推荐修复：L3 自动注入 answer==trace_answer 约束使不同答案 trace 必有冲突；L1 提取用 system prompt 强制 JSON-only。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T01:31:00.468Z\"}, \"sica_proofwriter30\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:08:42.831Z\", \"updated_at\": \"2026-05-15T22:18:19.326Z\", \"hypothesis\": \"逻辑域（ProofWriter D5）上 SICA 能否检测跨路径 FOL 约束矛盾并超越 SC@K=12——验证 SICA 在逻辑推理域的有效性\", \"parent\": \"sica_aime30_v3\", \"spec\": {\"command\": \"python eval_proofwriter.py --n-problems 30 --k 12 --max-tokens 16384 --seed 42 --save-intermediates --output results/proofwriter_30_eval.json\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"153924\", \"log_path\": \"/root/runs/symb_invariant_consensus/proofwriter30.log\", \"submitted_at\": \"2026-05-15T22:11:44.644Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_subset.json\", \"data_count\": 30, \"seed\": 42, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 16384, \"domain\": \"logic\", \"extraction_prompt\": \"LOGIC_EXTRACTION_PROMPT\", \"z3_timeout_s\": 60, \"checkpoint_source\": \"N/A (not eval - new SICA logic domain experiment)\", \"eval_data\": \"ProofWriter D5 30 problems (T:10 F:10 U:10)\", \"wall_clock_seconds\": 378.0, \"gpu_hours\": 0.1}, \"reproduce\": {\"finished_at\": \"2026-05-15T22:15:57.895Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:15:58.664228+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T22:18:02.631Z\", \"notes\": \"配置错误导致完全失败。--max-tokens 16384 等于 vLLM 的 --max-model-len 16384，prompt 输入空间为 0，所有 30 题从第 1 题起全部 400 Bad Request。没有生成任何 trace，没有提取约束，没有投票。4 分钟内跑完（全是 retry 耗时）。无法评估 sanity check 标准。需要用 --max-tokens 12288 或更小值重跑（AIME 实验用的 10240 正常工作）。\", \"metrics\": {\"sica_accuracy\": \"0/30 (0.0%)\", \"sc_accuracy\": \"0/30 (0.0%)\", \"sica_sc_gap_pp\": 0, \"total_wall_time_s\": 238.9, \"total_wall_time_min\": 4, \"avg_time_per_problem_s\": 8, \"traces_generated\": 0, \"constraints_extracted\": 0, \"traces_with_constraints\": 0, \"unique_constraints\": 0, \"maxsat_satisfied\": 0, \"maxsat_excluded\": 0, \"multi_candidate_rate\": \"N/A (no traces generated)\", \"vote_diversity\": \"N/A\", \"z3_errors\": 0, \"z3_timeouts\": 0, \"problems_with_contradiction\": 0, \"problems_with_votes\": 0, \"failure_mode\": \"ALL_400_BAD_REQUEST\", \"failure_count\": \"30/30\", \"root_cause\": \"max_tokens=16384 equals max_model_len=16384, leaving 0 tokens for prompt input. Every API call returns 400.\"}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/proofwriter_30_eval.json\", \"log_path\": \"/root/runs/symb_invariant_consensus/proofwriter30.log\"}, \"sica_aime30_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:13:04.296Z\", \"updated_at\": \"2026-05-15T22:07:55.967Z\", \"hypothesis\": \"AIME 2024 上 SICA 能否检测跨路径矛盾并超越 SC@K=12（v3: timeout=1800s, 从v2 P5恢复继续）\", \"spec\": {\"command\": \"PYTHONUNBUFFERED=1 python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 10240 --math-data data/aime2024_subset.json --output results/aime30_v2.json --no-proofwriter --seed 42 --resume\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"129992\", \"log_path\": \"/root/runs/symb_invariant_consensus/sica_aime30_v2_resume.log\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/aime2024_subset.json\", \"data_count\": 30, \"seed\": 42, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 10240, \"fixes\": \"timeout=1800s; n=4 batching on disk but not loaded by running process\", \"resumed_from\": \"sica_aime30_v2 (4/30 completed)\", \"remaining_problems\": 26}, \"parent\": \"sica_aime30_v2\", \"notes\": \"v3 killed at 22/30 (PID 129992, 6h11m). Vote diversity analysis: multi-candidate rate = 0.0%, all valid problems have exactly 1 candidate. SICA≡SC confirmed structural. 6/22 problems with 0 votes (extraction failure). 数学域结论锁定，转逻辑域。\", \"metrics\": {\"progress\": \"22/30\", \"sica_accuracy_interim\": \"16/22 (72.7%)\", \"sc_accuracy_interim\": \"16/22 (72.7%)\", \"sica_sc_gap_pp\": 0, \"avg_time_per_problem_s\": 645.9, \"runtime_h\": 5.9, \"remaining_problems\": 8, \"vote_diversity_analysis\": {\"valid_problems\": 16, \"total_problems\": 22, \"multi_candidate_rate\": 0, \"zero_vote_problems\": 6, \"zero_vote_indices\": [1, 7, 8, 10, 13, 14], \"constraints_extracted\": \"19/22\", \"exclusion_rate\": 0.387, \"conclusion\": \"All 16 valid problems have exactly 1 candidate answer. SICA≡SC structurally. MaxSAT exclusion operates but cannot change final selection with only 1 candidate.\"}, \"process_status\": \"gone (cron miss 1/5)\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T22:07:52.491Z\"}, \"sica_aime30_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:24:26.526Z\", \"updated_at\": \"2026-05-15T16:11:32.132Z\", \"spec\": {\"command\": \"PYTHONUNBUFFERED=1 python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 10240 --math-data data/aime2024_subset.json --output results/aime30_v2.json --no-proofwriter --seed 42\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"121139\", \"log_path\": \"/tmp/sica_aime30_v2.log\", \"submitted_at\": \"2026-05-15T13:24:26.512Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/aime2024_subset.json\", \"data_count\": 30, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 10240, \"seed\": null, \"seed_note\": \"--seed 42 在命令行中但 run_full_mvp.py 可能未实现该参数，实际 seed 未生效\", \"fixes\": \"timeout=120s HTTP, future timeout=180s, semaphore(6), vLLM health check\", \"wall_clock_seconds\": 8899.6, \"gpu_hours\": 2.47}, \"hypothesis\": \"AIME 2024 上 SICA 能否检测跨路径矛盾并超越 SC@K=12（v2: 修复 timeout/hang bug 后重跑）\", \"conclusion\": \"killed\", \"metrics\": {\"progress\": \"4/30\", \"sica_accuracy_interim\": \"3/4 (75%)\", \"sc_accuracy_interim\": \"3/4 (75%)\", \"avg_time_per_problem_s\": 557, \"p2_z3_error\": \"Z3Exception on z3_maxsat.py:163, 0 constraints extracted\", \"p5_vllm_stuck\": \"vLLM timeout since ~22:11, retried multiple rounds\", \"issue\": \"vLLM service likely crashed or OOM at Problem 5\", \"analysis_contradiction_rate_aime\": \"50% (2/4)\", \"analysis_contradiction_rate_math\": \"20% (1/5)\", \"analysis_unique_constraints_per_problem_aime\": 18.7, \"analysis_exclusion_rate\": \"10.7%\", \"analysis_sica_sc_agreement\": \"9/9 (100%)\", \"analysis_signal\": \"weak positive - mechanism works but SC too unanimous to flip\", \"analysis_p2_failure\": \"0 constraints, 0 votes - answer extraction failure\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:52:45.450Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-15T15:52:46.068Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:52:46.737218+00:00\"}]}, \"notes\": \"失败原因: Problem 5 (aime2024_II_05, 凸六边形几何题) 12条并发trace在单GPU上竞争资源→每条trace吞吐极低→客户端~600s超时后重试→旧请求仍在vLLM running→恶性循环卡死~1h47min | 已有成果: 4/30题完成 SICA 3/4=75% SC 3/4=75%, P2有Z3Exception(0 constraints extracted) | vLLM本身健康(test request <1s) | 建议: 降低并发k或分批处理trace(如4条/批), 增大client timeout, kill stuck requests后重启\"}, \"sica_aime30_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:38:16.330Z\", \"updated_at\": \"2026-05-15T13:11:37.911Z\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 10240 --math-data data/aime2024_subset.json --output results/aime30_t07.json --no-proofwriter\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"119338\", \"log_path\": \"~/runs/symb_invariant_consensus/sica_aime30_t07.log\", \"submitted_at\": \"2026-05-15T13:01:07.184Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/aime2024_subset.json\", \"data_count\": 30, \"model_name\": \"QwQ-32B\", \"seed\": null, \"wall_clock_seconds\": 630.7, \"gpu_hours\": 0.18}, \"hypothesis\": \"AIME 2024（QwQ-32B 弱项，~79.5% acc）上 SICA 能否检测更多跨路径矛盾并超越 SC@K=12——验证\\\"SICA 价值随问题难度递增\\\"假设\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T13:11:37.911Z\"}, \"mvp_math50_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:16:29.416Z\", \"updated_at\": \"2026-05-15T12:21:37.283Z\", \"spec\": {\"command\": \"nohup python3 run_full_mvp.py --mode vllm --k 12 --output results/mvp_math50_t07.json > /tmp/mvp_math50.log 2>&1 &\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/math500_subset.json\", \"data_count\": 50, \"model_name\": \"QwQ-32B\", \"seed\": 42, \"method\": \"SICA\", \"checkpoint_path\": \"results/mvp_math50_t07.json\", \"log_path\": \"/tmp/mvp_math50.log\", \"temperature\": 0.7, \"k\": 12}, \"hypothesis\": \"SICA MVP: 50题MATH-500上跨路径MAX-SAT约束共识能否检测矛盾并超越SC@K=12\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:21:37.283Z\"}, \"sica_smoke_5q\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:38:43.996Z\", \"updated_at\": \"2026-05-15T11:39:13.456Z\", \"spec\": {\"command\": \"python3 smoke_test_5q.py (nohup)\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/math500_subset.json\", \"data_count\": 5, \"model_name\": \"QwQ-32B\", \"seed\": 42, \"method\": \"SICA\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/smoke_test_5q.log\"}, \"hypothesis\": \"SICA smoke test: 验证端到端 pipeline 可行性（5题 MATH-500, K=12, QwQ-32B）\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T11:39:07.006Z\", \"metrics\": {\"sica_accuracy\": 0.8, \"sc_accuracy\": 0.8, \"extraction_rate\": 1, \"problems_with_contradictions\": 1, \"total_problems\": 5, \"total_time_s\": 3505, \"avg_time_per_problem_s\": 701, \"per_problem\": [{\"id\": \"algebra/2470\", \"level\": 1, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 27, \"unique\": 9, \"excluded\": 0}, {\"id\": \"prealgebra/65\", \"level\": 2, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 26, \"unique\": 2, \"excluded\": 0}, {\"id\": \"number_theory/847\", \"level\": 3, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 21, \"unique\": 11, \"excluded\": 0, \"note\": \"14 JSON parse failures, 1693s\"}, {\"id\": \"precalculus/1199\", \"level\": 4, \"sica_correct\": false, \"sc_correct\": false, \"constraints\": 35, \"unique\": 6, \"excluded\": 0, \"note\": \"graph-reading problem, model cannot see image\"}, {\"id\": \"algebra/2277\", \"level\": 5, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 60, \"unique\": 6, \"satisfied\": 3, \"excluded\": 3}]}}, \"smoke-test-5q\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:22:09.665Z\", \"updated_at\": \"2026-05-15T11:22:09.666Z\", \"conclusion\": \"failed\"}, \"crd_folio_main\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:35:42.037Z\", \"updated_at\": \"2026-05-15T09:36:24.832Z\", \"spec\": {\"command\": \"python run_pipeline.py (CRD dual-representation pipeline)\", \"server\": \"westd-32608\", \"data_path\": \"/root/autodl-tmp/crdd/results/mvp_v4_full.jsonl\", \"data_count\": 204, \"model_name\": \"Qwen3-32B-AWQ\", \"seed\": 42, \"method\": \"CRD\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/crdd/results/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T09:36:03.793Z\", \"hypothesis\": \"CRD: 双表征(FOL+SymPy)分歧检测+定向修复能提升逻辑推理准确率（非SICA方法）\", \"metrics\": {\"divergence_rate\": 0.422, \"diagnosis_rate\": 0.872, \"error_types\": 4, \"directed_advantage_pp\": 4.7, \"directed_p_value\": 0.63, \"localization_accuracy\": 0.946, \"fol_accuracy\": 0.789, \"code_accuracy\": 0.598, \"oracle_accuracy\": 0.878, \"pipeline_accuracy\": 0.814, \"baseline_accuracy\": 0.74, \"cost_multiplier\": 5.76, \"dataset\": \"FOLIO\", \"n\": 204}}}, \"count\": 176, \"total\": 176, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4821}}"
    }
  },
  "sourceToolAssistantUUID": "26584dc6-d3d1-44ec-94f9-311d58cc9d1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool result

_source line 15 · 2026-05-24T04:28:36.214Z_

<details><summary>↩ Tool result · `toolu_01RW5tfk8GKcdGAXAnhGg9sK`</summary>

```text
1	\section{Related Work}
2	\label{sec:related-work}
3	
4	\looseness=-1
5	\paragraph{Self-consistency and ensemble theory.}
6	Self-consistency (SC) selects the most frequent answer across chain-of-thought traces \citep{wang2023sc}. Extensions address free-form generation \citep{chen2024usc}, confidence weighting \citep{taubenfeld2025cisc}, diverse prompting \citep{li2023diverse}, and reasoning-aware filtering \citep{wan2024rasc, toh2024notallvotes, kim2026reasc}. SC gains plateau early \citep{loo2025reevaluating, byerly2025selfconsistency}. The Condorcet Jury Theorem \citep{condorcet1785} guarantees majority-vote convergence under independence; ensemble theory \citep{dietterich2000ensemble, krogh1994neural} establishes that ensemble gain requires error diversity. \citet{ladha1992correlated} show correlated voters reduce effective ensemble size; our $K_\text{eff}$ adapts Fleiss' $\kappa$ from diversity metrics \citep{kuncheva2003measures, brown2005diversity} to quantify this compression (\S\ref{sec:pipeline}). \citet{kim2025correlated} demonstrate correlated errors in LLM outputs; \citet{kuai2026independent} propose cross-model independence auditing, complementary to our within-model process-$\kappa$.
7	
8	\looseness=-1
9	\paragraph{Neuro-symbolic reasoning.}
10	We distinguish three paradigms: \emph{specification-generation} \citep{pan2023logiclm, olausson2023linc, ye2024satlm} and \emph{program-generation} \citep{gao2023pal, chen2023program, lyu2023faithful} formalize \emph{before} answer generation; \emph{trace-extraction} (this work) operates post-hoc, inheriting confirmation bias (\S\ref{sec:confirmation-bias}). Recent extensions include symbolic planning and verified reasoning \citep{ryu2025clover, xu2026dylos, li2025aristotle, wang2025fover, singh2026verge, luo2025logicagent, miya2025eidoku}; \citet{amonkar2025realitycheck} show formalization quality degrades with problem complexity; \citet{chan2026position} argue logical soundness alone is unreliable. Prior studies note high formalization error rates but treat them as quality problems; we show the errors are \emph{systematically biased} toward the model's answer (Observation~1; Figure~\ref{fig:causal-dag}). Our analysis reveals a deeper mechanism underlying \citet{huang2024selfcorrect}'s finding that LLMs cannot self-correct without external feedback, showing that even Z3-validated constraints carry no information beyond majority voting.
11	
12	\looseness=-1
13	\paragraph{Distinction from CoT confirmation bias.}
14	Symbolic confirmation bias (SCB) is complementary to, but structurally distinct from, CoT-level confirmation bias \citep{wan2025unveiling, turpin2023language, jhaveri2026failing}. CoT bias operates at the \emph{trace level}---individual chains may not faithfully reflect the model's computation---while SCB operates at the \emph{aggregation level}: even if each trace is locally faithful, the \emph{collection} of self-extracted constraints mirrors the answer distribution.
15	
16	\looseness=-1
17	\paragraph{Relationship to \citet{huang2024selfcorrect}.}
18	\citeauthor{huang2024selfcorrect} empirically demonstrate that LLMs cannot self-correct reasoning without external feedback; our work reveals a deeper mechanism underlying this finding. Where they report the phenomenon through evaluation of prompting strategies, we formalize the failure via the $M{\to}T{\to}A{\to}C$ Markov chain (Observation~1) that explains \emph{why} self-correction fails. Where they lack tools for a priori prediction, we provide three zero-cost diagnostics ($K_\text{eff}$, BR, $C_0$) that predict failure modes before deployment. Where they do not test formal verification, we systematically evaluate 27 training-free variants including Z3-validated constraints, showing that even provably sound solvers cannot escape the bottleneck.
19	
20	\looseness=-1
21	\paragraph{Test-time compute and self-verification.}
22	Scaling test-time compute via additional traces \citep{snell2025scaling}, structured search \citep{yao2023tree}, or extended reasoning (DeepSeek-R1 \citep{guo2025deepseekr1}, QwQ \citep{qwen2024qwq}, OpenAI o1/o3) faces the same correlation challenge when traces share a single model's biases. Multi-agent debate \citep{liang2023encouraging, du2023improving}, self-evaluation and refinement \citep{xie2023selfevaluation, weng2023selfverification, madaan2023selfrefine, dhuliawala2023chainofverification}, iterative self-improvement \citep{shinn2023reflexion, zhou2023lats}, tool-augmented critique \citep{gou2024critic}, formal CoT verification \citep{zhu2025vericot, chen2025sets}, and multi-agent verification \citep{lifshitz2025mav} report gains, but none tests self-extracted constraints under formal solvers \citep[cf.][]{kamoi2024selfcorrect}. We find the bottleneck lies in constraint extraction, not verification: self-extracted constraints inherit the model's bias regardless of solver soundness (\S\ref{sec:confirmation-bias}). Oracle controls confirm the verification mechanism itself is sound (Appendix~\ref{app:oracle}).
23	
24	\looseness=-1
25	\paragraph{Training-based verification.}
26	Trained verifiers escape the self-extraction bottleneck via external reward signals: outcome and process reward models \citep{cobbe2021gsm8k, lightman2024prm, wang2024mathshepherd}, discriminator-guided decoding \citep{khalifa2023grace}, RL-based self-verification \citep{zeng2025s2r}, dual preference optimization \citep{dupo2025}, and execution-based filtering \citep{li2022alphacode, chen2023codet}. These operate outside the pipeline of Observation~1, potentially breaking the DPI bound by violating the trace-determined assumption. The failure modes differ: SICA's bottleneck is extraction fidelity (constraints echo the model's prior), whereas PRM/ORM's is reward model generalization \citep{wang2024mathshepherd}. Our diagnostics (BR, $K_\text{eff}$) may extend to learned verification by quantifying whether learned scores introduce genuine independence.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2d81bdd4-04f1-4017-a174-42b70bc00faf",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "e25538cb-68a3-432c-856c-f837f7b10cc8",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\looseness=-1\n\\paragraph{Self-consistency and ensemble theory.}\nSelf-consistency (SC) selects the most frequent answer across chain-of-thought traces \\citep{wang2023sc}. Extensions address free-form generation \\citep{chen2024usc}, confidence weighting \\citep{taubenfeld2025cisc}, diverse prompting \\citep{li2023diverse}, and reasoning-aware filtering \\citep{wan2024rasc, toh2024notallvotes, kim2026reasc}. SC gains plateau early \\citep{loo2025reevaluating, byerly2025selfconsistency}. The Condorcet Jury Theorem \\citep{condorcet1785} guarantees majority-vote convergence under independence; ensemble theory \\citep{dietterich2000ensemble, krogh1994neural} establishes that ensemble gain requires error diversity. \\citet{ladha1992correlated} show correlated voters reduce effective ensemble size; our $K_\\text{eff}$ adapts Fleiss' $\\kappa$ from diversity metrics \\citep{kuncheva2003measures, brown2005diversity} to quantify this compression (\\S\\ref{sec:pipeline}). \\citet{kim2025correlated} demonstrate correlated errors in LLM outputs; \\citet{kuai2026independent} propose cross-model independence auditing, complementary to our within-model process-$\\kappa$.\n\n\\looseness=-1\n\\paragraph{Neuro-symbolic reasoning.}\nWe distinguish three paradigms: \\emph{specification-generation} \\citep{pan2023logiclm, olausson2023linc, ye2024satlm} and \\emph{program-generation} \\citep{gao2023pal, chen2023program, lyu2023faithful} formalize \\emph{before} answer generation; \\emph{trace-extraction} (this work) operates post-hoc, inheriting confirmation bias (\\S\\ref{sec:confirmation-bias}). Recent extensions include symbolic planning and verified reasoning \\citep{ryu2025clover, xu2026dylos, li2025aristotle, wang2025fover, singh2026verge, luo2025logicagent, miya2025eidoku}; \\citet{amonkar2025realitycheck} show formalization quality degrades with problem complexity; \\citet{chan2026position} argue logical soundness alone is unreliable. Prior studies note high formalization error rates but treat them as quality problems; we show the errors are \\emph{systematically biased} toward the model's answer (Observation~1; Figure~\\ref{fig:causal-dag}). Our analysis reveals a deeper mechanism underlying \\citet{huang2024selfcorrect}'s finding that LLMs cannot self-correct without external feedback, showing that even Z3-validated constraints carry no information beyond majority voting.\n\n\\looseness=-1\n\\paragraph{Distinction from CoT confirmation bias.}\nSymbolic confirmation bias (SCB) is complementary to, but structurally distinct from, CoT-level confirmation bias \\citep{wan2025unveiling, turpin2023language, jhaveri2026failing}. CoT bias operates at the \\emph{trace level}---individual chains may not faithfully reflect the model's computation---while SCB operates at the \\emph{aggregation level}: even if each trace is locally faithful, the \\emph{collection} of self-extracted constraints mirrors the answer distribution.\n\n\\looseness=-1\n\\paragraph{Relationship to \\citet{huang2024selfcorrect}.}\n\\citeauthor{huang2024selfcorrect} empirically demonstrate that LLMs cannot self-correct reasoning without external feedback; our work reveals a deeper mechanism underlying this finding. Where they report the phenomenon through evaluation of prompting strategies, we formalize the failure via the $M{\\to}T{\\to}A{\\to}C$ Markov chain (Observation~1) that explains \\emph{why} self-correction fails. Where they lack tools for a priori prediction, we provide three zero-cost diagnostics ($K_\\text{eff}$, BR, $C_0$) that predict failure modes before deployment. Where they do not test formal verification, we systematically evaluate 27 training-free variants including Z3-validated constraints, showing that even provably sound solvers cannot escape the bottleneck.\n\n\\looseness=-1\n\\paragraph{Test-time compute and self-verification.}\nScaling test-time compute via additional traces \\citep{snell2025scaling}, structured search \\citep{yao2023tree}, or extended reasoning (DeepSeek-R1 \\citep{guo2025deepseekr1}, QwQ \\citep{qwen2024qwq}, OpenAI o1/o3) faces the same correlation challenge when traces share a single model's biases. Multi-agent debate \\citep{liang2023encouraging, du2023improving}, self-evaluation and refinement \\citep{xie2023selfevaluation, weng2023selfverification, madaan2023selfrefine, dhuliawala2023chainofverification}, iterative self-improvement \\citep{shinn2023reflexion, zhou2023lats}, tool-augmented critique \\citep{gou2024critic}, formal CoT verification \\citep{zhu2025vericot, chen2025sets}, and multi-agent verification \\citep{lifshitz2025mav} report gains, but none tests self-extracted constraints under formal solvers \\citep[cf.][]{kamoi2024selfcorrect}. We find the bottleneck lies in constraint extraction, not verification: self-extracted constraints inherit the model's bias regardless of solver soundness (\\S\\ref{sec:confirmation-bias}). Oracle controls confirm the verification mechanism itself is sound (Appendix~\\ref{app:oracle}).\n\n\\looseness=-1\n\\paragraph{Training-based verification.}\nTrained verifiers escape the self-extraction bottleneck via external reward signals: outcome and process reward models \\citep{cobbe2021gsm8k, lightman2024prm, wang2024mathshepherd}, discriminator-guided decoding \\citep{khalifa2023grace}, RL-based self-verification \\citep{zeng2025s2r}, dual preference optimization \\citep{dupo2025}, and execution-based filtering \\citep{li2022alphacode, chen2023codet}. These operate outside the pipeline of Observation~1, potentially breaking the DPI bound by violating the trace-determined assumption. The failure modes differ: SICA's bottleneck is extraction fidelity (constraints echo the model's prior), whereas PRM/ORM's is reward model generalization \\citep{wang2024mathshepherd}. Our diagnostics (BR, $K_\\text{eff}$) may extend to learned verification by quantifying whether learned scores introduce genuine independence.",
      "numLines": 26,
      "startLine": 1,
      "totalLines": 26
    }
  },
  "sourceToolAssistantUUID": "2d81bdd4-04f1-4017-a174-42b70bc00faf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 16 · 2026-05-24T04:28:30.199Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FtbDNaeLLCDdkD2tXBwbxN`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "03a69143-1125-4f46-a9f9-306a0f7931ca",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "d53c7149-6a3d-4905-a556-9877ee5f1e9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 17 · 2026-05-24T04:28:30.210Z_

<details><summary>↩ Tool result · `toolu_01FtbDNaeLLCDdkD2tXBwbxN`</summary>

```text
1	Can symbolic verification via a provably sound solver improve Large Language Model (LLM) reasoning when constraints are self-extracted from the model's own traces? Across six confirmatory conditions ($n \geq 200$), we find no detectable improvement exceeding ${\sim}$2 percentage points (pp). We introduce Symbolic Invariant Consensus Aggregation (SICA), which extracts logical constraints from chain-of-thought traces via weighted MAX-SAT. Despite Z3 validating 99\% of self-extracted constraints, SICA matches majority voting on over 90\% of problems across six models (7B--32B) and four benchmarks. No condition shows a significant positive effect after FDR control; four of six powered conditions confirm equivalence within $\pm$2\,pp (TOST); the remainder are underpowered for smaller effects. The failure is a robust empirical regularity: self-extracted constraints track the majority answer---a property we term \emph{symbolic confirmation bias} (bias ratios $1.66$--$4.97\times$ across nine models, 7B to frontier). Under source-attribution scoring and degeneration, SICA reduces to majority vote (Observation~1); the $M{\to}T{\to}A{\to}C$ Markov chain bounds self-extracted information, revealing a deeper mechanism underlying \citet{huang2024selfcorrect}'s findings. Twenty-seven training-free variants fail due to a persistent independence-accuracy trade-off. As exploratory evidence, cross-architecture verification escapes the bias ($+6.67$\,pp on the weakest generator, $p < 0.001$). Three zero-cost diagnostics characterize failure modes across all tested conditions.
2	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d53c7149-6a3d-4905-a556-9877ee5f1e9f",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "f2a0c085-77ed-4357-bfb4-596ebfe4bed7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
      "content": "Can symbolic verification via a provably sound solver improve Large Language Model (LLM) reasoning when constraints are self-extracted from the model's own traces? Across six confirmatory conditions ($n \\geq 200$), we find no detectable improvement exceeding ${\\sim}$2 percentage points (pp). We introduce Symbolic Invariant Consensus Aggregation (SICA), which extracts logical constraints from chain-of-thought traces via weighted MAX-SAT. Despite Z3 validating 99\\% of self-extracted constraints, SICA matches majority voting on over 90\\% of problems across six models (7B--32B) and four benchmarks. No condition shows a significant positive effect after FDR control; four of six powered conditions confirm equivalence within $\\pm$2\\,pp (TOST); the remainder are underpowered for smaller effects. The failure is a robust empirical regularity: self-extracted constraints track the majority answer---a property we term \\emph{symbolic confirmation bias} (bias ratios $1.66$--$4.97\\times$ across nine models, 7B to frontier). Under source-attribution scoring and degeneration, SICA reduces to majority vote (Observation~1); the $M{\\to}T{\\to}A{\\to}C$ Markov chain bounds self-extracted information, revealing a deeper mechanism underlying \\citet{huang2024selfcorrect}'s findings. Twenty-seven training-free variants fail due to a persistent independence-accuracy trade-off. As exploratory evidence, cross-architecture verification escapes the bias ($+6.67$\\,pp on the weakest generator, $p < 0.001$). Three zero-cost diagnostics characterize failure modes across all tested conditions.\n",
      "numLines": 2,
      "startLine": 1,
      "totalLines": 2
    }
  },
  "sourceToolAssistantUUID": "d53c7149-6a3d-4905-a556-9877ee5f1e9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 18 · 2026-05-24T04:28:30.754Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DRL1qvXwrMYQLsD2VFQ6kM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f2a0c085-77ed-4357-bfb4-596ebfe4bed7",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "31009d24-14f1-46b1-a59e-82f264526f29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 19 · 2026-05-24T04:28:30.759Z_

<details><summary>↩ Tool result · `toolu_01DRL1qvXwrMYQLsD2VFQ6kM`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	\looseness=-1
4	Self-Consistency (SC) \citep{wang2023sc} selects the majority answer across $K$ chain-of-thought traces, a strategy grounded in the Condorcet Jury Theorem: independent voters converge to truth \citep{condorcet1785, ladha1992correlated}. In practice, SC's gains plateau for strong models \citep{loo2025reevaluating}, pointing to correlated traces that reduce the effective ensemble size. A natural remedy is to move beyond simple vote-counting: extract logical constraints from the traces and let a provably sound solver adjudicate. If the solver can filter contradictions and enforce logical consistency, it should recover information that raw majority voting discards.
5	
6	\looseness=-1
7	We test this intuition through Symbolic Invariant Consensus Aggregation (SICA), which extracts logical constraints from reasoning traces (prompted as first-order logic; 99\% are propositional at the Z3 level) and selects answers via weighted partial MAX-SAT (\S\ref{sec:pipeline}; Figure~\ref{fig:pipeline}). Despite Z3 validating nearly all self-extracted constraints, SICA produces answers identical to majority voting on the vast majority of problems. Across six models (7B--32B), four benchmarks, and multi-seed replication, no condition shows a significant positive effect after FDR control (Table~\ref{tab:main_results}). Four of six powered conditions confirm equivalence within $\pm$2\,pp (TOST); the remainder are underpowered for smaller effects.
8	
9	\looseness=-1
10	The failure is not in the solver but in the constraints it operates on. Self-extracted constraints systematically support the model's majority answer---a robust empirical regularity of zero-shot self-extraction pipelines we term \emph{symbolic confirmation bias} (\S\ref{sec:confirmation-bias}). Because each trace determines both an answer and its constraints, the formal channel reduces to a weighted echo of the majority vote. We show this degeneration is robust (Observation~1) and confirm it holds across nine models from 7B to frontier scale. Prior work shows LLMs cannot self-correct reasoning without external feedback \citep{huang2024selfcorrect}; our analysis reveals a deeper mechanism underlying these findings, providing a Markov chain formalization and actionable diagnostics for self-verification.
11	
12	\looseness=-1
13	Twenty-seven training-free variants within the constraint-extraction paradigm confirm the trade-off is fundamental (\S\ref{sec:remediation}): methods that break trace correlation destroy accuracy, while methods that preserve accuracy fail to achieve independence. Cross-architecture verification provides preliminary evidence of escape: a structurally independent verifier yields significant gains when it exceeds the generator's accuracy, with benefit governed by a capability-gap pattern between verifier and generator (\S\ref{sec:cross-arch}). Three zero-cost diagnostics enable practitioners to predict a priori whether any self-extraction-based aggregation method will help (\S\ref{sec:diagnostic-framework}).
14	
15	Our contributions are:
16	\begin{enumerate}[nosep,leftmargin=*]
17	\item \textbf{The symbolic mirage.} Provably sound Z3 verification becomes vacuous under self-extraction. We diagnose the underlying mechanism: self-extracted constraints inherit the generating model's distributional prior (symbolic confirmation bias), reducing SICA to majority vote under source-attribution scoring (Observation~1). The pattern holds across nine models and 27 training-free variants (\S\ref{sec:confirmation-bias}, \S\ref{sec:remediation}).\footnote{Code and data will be released upon acceptance.}
18	
19	\item \textbf{Diagnostic framework.} Three zero-cost diagnostics characterize failure modes across all tested conditions within the self-extraction paradigm, with prospective validation on held-out model families, providing practitioners with a priori failure-mode diagnosis from a pilot run (\S\ref{sec:diagnostic-framework}).
20	
21	\item \textbf{Cross-architecture escape.} Preliminary evidence that structurally independent verification can break the bottleneck, with gain governed by a capability-gap pattern between verifier and generator (\S\ref{sec:cross-arch}).
22	\end{enumerate}
23	
24	\begin{figure}[t]
25	\centering
26	\small
27	\resizebox{\columnwidth}{!}{\begin{tikzpicture}[
28	    node distance=0.3cm and 0.1cm,
29	    box/.style={draw, rounded corners=2pt, minimum height=0.55cm,
30	                text width=1.2cm, align=center, font=\scriptsize},
31	    arr/.style={-{Stealth[length=4pt]}, thick},
32	    darr/.style={-{Stealth[length=4pt]}, thick, densely dashed},
33	    lbl/.style={font=\scriptsize, text=gray!70!black},
34	    ibottle/.style={draw=red!70!black, densely dashed, rounded corners=3pt,
35	                    inner sep=3pt},
36	]
37	\node[box] (q) {Question $q$};
38	\node[box, right=of q] (sample) {Sample $K$\\traces};
39	\node[box, right=of sample] (extract) {Extract logical\\constraints};
40	\node[box, right=of extract] (dedup) {Dedup.\ +\\weight};
41	\node[box, right=of dedup] (maxsat) {MAX-SAT\\(Z3)};
42	
43	\node[box, below=0.7cm of maxsat, fill=gray!12] (ans) {Answer $a^*$};
44	\node[box, below=0.7cm of sample, fill=gray!12] (sc) {Majority\\vote};
45	
46	\draw[arr] (q) -- (sample);
47	\draw[arr] (sample) -- (extract);
48	\draw[arr] (extract) -- (dedup);
49	\draw[arr] (dedup) -- (maxsat);
50	\draw[arr] (maxsat) -- (ans);
51	\draw[arr] (sample) -- node[lbl, right, yshift=0pt] {SC} (sc);
52	
53	\node[lbl, above=0.01cm of maxsat] {SICA};
54	
55	\node[ibottle, fit=(sample)(extract), label={[font=\scriptsize\itshape, text=red!70!black]above:Independence Bottleneck}] {};
56	
57	\draw[darr, gray!60] ([xshift=-0.1cm]dedup.south) -- ++(0,-0.35) node[lbl, below, yshift=-0.05cm] {oracle: gold FOL};
58	\end{tikzpicture}}
59	\caption{The SICA pipeline. SC selects the majority answer from $K$ traces. SICA extracts logical constraints, deduplicates, and solves MAX-SAT via Z3. Red dashed box: the independence bottleneck. Dashed arrow: oracle variant with gold FOL.}
60	\label{fig:pipeline}
61	\end{figure}
62	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "31009d24-14f1-46b1-a59e-82f264526f29",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "bbe1ffa1-487b-4900-a6c8-2b17b637fbe1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\\label{sec:introduction}\n\n\\looseness=-1\nSelf-Consistency (SC) \\citep{wang2023sc} selects the majority answer across $K$ chain-of-thought traces, a strategy grounded in the Condorcet Jury Theorem: independent voters converge to truth \\citep{condorcet1785, ladha1992correlated}. In practice, SC's gains plateau for strong models \\citep{loo2025reevaluating}, pointing to correlated traces that reduce the effective ensemble size. A natural remedy is to move beyond simple vote-counting: extract logical constraints from the traces and let a provably sound solver adjudicate. If the solver can filter contradictions and enforce logical consistency, it should recover information that raw majority voting discards.\n\n\\looseness=-1\nWe test this intuition through Symbolic Invariant Consensus Aggregation (SICA), which extracts logical constraints from reasoning traces (prompted as first-order logic; 99\\% are propositional at the Z3 level) and selects answers via weighted partial MAX-SAT (\\S\\ref{sec:pipeline}; Figure~\\ref{fig:pipeline}). Despite Z3 validating nearly all self-extracted constraints, SICA produces answers identical to majority voting on the vast majority of problems. Across six models (7B--32B), four benchmarks, and multi-seed replication, no condition shows a significant positive effect after FDR control (Table~\\ref{tab:main_results}). Four of six powered conditions confirm equivalence within $\\pm$2\\,pp (TOST); the remainder are underpowered for smaller effects.\n\n\\looseness=-1\nThe failure is not in the solver but in the constraints it operates on. Self-extracted constraints systematically support the model's majority answer---a robust empirical regularity of zero-shot self-extraction pipelines we term \\emph{symbolic confirmation bias} (\\S\\ref{sec:confirmation-bias}). Because each trace determines both an answer and its constraints, the formal channel reduces to a weighted echo of the majority vote. We show this degeneration is robust (Observation~1) and confirm it holds across nine models from 7B to frontier scale. Prior work shows LLMs cannot self-correct reasoning without external feedback \\citep{huang2024selfcorrect}; our analysis reveals a deeper mechanism underlying these findings, providing a Markov chain formalization and actionable diagnostics for self-verification.\n\n\\looseness=-1\nTwenty-seven training-free variants within the constraint-extraction paradigm confirm the trade-off is fundamental (\\S\\ref{sec:remediation}): methods that break trace correlation destroy accuracy, while methods that preserve accuracy fail to achieve independence. Cross-architecture verification provides preliminary evidence of escape: a structurally independent verifier yields significant gains when it exceeds the generator's accuracy, with benefit governed by a capability-gap pattern between verifier and generator (\\S\\ref{sec:cross-arch}). Three zero-cost diagnostics enable practitioners to predict a priori whether any self-extraction-based aggregation method will help (\\S\\ref{sec:diagnostic-framework}).\n\nOur contributions are:\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{The symbolic mirage.} Provably sound Z3 verification becomes vacuous under self-extraction. We diagnose the underlying mechanism: self-extracted constraints inherit the generating model's distributional prior (symbolic confirmation bias), reducing SICA to majority vote under source-attribution scoring (Observation~1). The pattern holds across nine models and 27 training-free variants (\\S\\ref{sec:confirmation-bias}, \\S\\ref{sec:remediation}).\\footnote{Code and data will be released upon acceptance.}\n\n\\item \\textbf{Diagnostic framework.} Three zero-cost diagnostics characterize failure modes across all tested conditions within the self-extraction paradigm, with prospective validation on held-out model families, providing practitioners with a priori failure-mode diagnosis from a pilot run (\\S\\ref{sec:diagnostic-framework}).\n\n\\item \\textbf{Cross-architecture escape.} Preliminary evidence that structurally independent verification can break the bottleneck, with gain governed by a capability-gap pattern between verifier and generator (\\S\\ref{sec:cross-arch}).\n\\end{enumerate}\n\n\\begin{figure}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{\\begin{tikzpicture}[\n    node distance=0.3cm and 0.1cm,\n    box/.style={draw, rounded corners=2pt, minimum height=0.55cm,\n                text width=1.2cm, align=center, font=\\scriptsize},\n    arr/.style={-{Stealth[length=4pt]}, thick},\n    darr/.style={-{Stealth[length=4pt]}, thick, densely dashed},\n    lbl/.style={font=\\scriptsize, text=gray!70!black},\n    ibottle/.style={draw=red!70!black, densely dashed, rounded corners=3pt,\n                    inner sep=3pt},\n]\n\\node[box] (q) {Question $q$};\n\\node[box, right=of q] (sample) {Sample $K$\\\\traces};\n\\node[box, right=of sample] (extract) {Extract logical\\\\constraints};\n\\node[box, right=of extract] (dedup) {Dedup.\\ +\\\\weight};\n\\node[box, right=of dedup] (maxsat) {MAX-SAT\\\\(Z3)};\n\n\\node[box, below=0.7cm of maxsat, fill=gray!12] (ans) {Answer $a^*$};\n\\node[box, below=0.7cm of sample, fill=gray!12] (sc) {Majority\\\\vote};\n\n\\draw[arr] (q) -- (sample);\n\\draw[arr] (sample) -- (extract);\n\\draw[arr] (extract) -- (dedup);\n\\draw[arr] (dedup) -- (maxsat);\n\\draw[arr] (maxsat) -- (ans);\n\\draw[arr] (sample) -- node[lbl, right, yshift=0pt] {SC} (sc);\n\n\\node[lbl, above=0.01cm of maxsat] {SICA};\n\n\\node[ibottle, fit=(sample)(extract), label={[font=\\scriptsize\\itshape, text=red!70!black]above:Independence Bottleneck}] {};\n\n\\draw[darr, gray!60] ([xshift=-0.1cm]dedup.south) -- ++(0,-0.35) node[lbl, below, yshift=-0.05cm] {oracle: gold FOL};\n\\end{tikzpicture}}\n\\caption{The SICA pipeline. SC selects the majority answer from $K$ traces. SICA extracts logical constraints, deduplicates, and solves MAX-SAT via Z3. Red dashed box: the independence bottleneck. Dashed arrow: oracle variant with gold FOL.}\n\\label{fig:pipeline}\n\\end{figure}\n",
      "numLines": 62,
      "startLine": 1,
      "totalLines": 62
    }
  },
  "sourceToolAssistantUUID": "31009d24-14f1-46b1-a59e-82f264526f29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 20 · 2026-05-24T04:28:31.973Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RVKdvHDxpXqSoCnym9i3vi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bbe1ffa1-487b-4900-a6c8-2b17b637fbe1",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "aa14a2d8-6411-4b53-a17d-67e4b45e38b9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 21 · 2026-05-24T04:28:31.977Z_

<details><summary>↩ Tool result · `toolu_01RVKdvHDxpXqSoCnym9i3vi`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{SICA Pipeline}
5	\label{sec:pipeline}
6	\label{sec:condorcet}
7	\label{sec:effective-k}
8	
9	Self-Consistency (SC) \citep{wang2023sc} samples $K$ reasoning traces and selects the majority answer. Under correlated traces (Fleiss' $\kappa$ \citep{fleiss1971kappa}), effective sample size reduces to
10	\begin{equation}
11	\label{eq:effk}
12	K_{\text{eff}} = K \,/\, [1 + (K{-}1) \cdot \kappa]
13	\end{equation}
14	(following \citet{ladha1992correlated}). Intuitively, $K_\text{eff}$ measures how many effectively independent votes $K$ correlated traces contribute; e.g., $K{=}12$ traces with $\kappa{=}0.69$ yield $K_\text{eff} \approx 1.3$, meaning twelve correlated traces carry no more independent information than 1.3 uncorrelated ones. This motivates constraint-based aggregation.
15	
16	Symbolic Invariant Consensus Aggregation (SICA) extends SC by extracting formal constraints from traces and selecting the answer best supported by the satisfiable subset (Figure~\ref{fig:pipeline}).
17	
18	\paragraph{Trace generation.} Given question $q$, an LLM generates $K$ traces $\{t_1, \ldots, t_K\}$ at temperature $T = 0.7$. Each trace $t_i$ yields answer $a_i$.
19	
20	\looseness=-1
21	\paragraph{Constraint extraction.}\label{sec:constraint-extraction} The same LLM extracts logical constraints from each trace at $T_{\text{ext}} = 0.3$. The extraction prompt requests JSON output with constraint type, expression, and Z3-compatible formula (Appendix~\ref{app:prompts}); in practice, 99.0\% of extracted constraints are propositional at the Z3 level, with only 1.0\% using true quantifiers. The \emph{extraction rate} is the fraction of traces yielding at least one parseable constraint.
22	
23	\paragraph{Deduplication and MAX-SAT.} Constraints are deduplicated by syntactic equivalence (global average deduplication ratio: 46.0\%); each unique constraint $c_m$ receives weight $w_m$ equal to the number of source traces. The objective finds the largest-weight satisfiable subset:
24	\begin{equation}
25	\label{eq:maxsat}
26	\mathcal{C}^* = \arg\max_{\mathcal{S} \subseteq \mathcal{C}} \sum_{c \in \mathcal{S}} w_c \quad \text{s.t.} \quad \mathcal{S} \text{ is satisfiable.}
27	\end{equation}
28	Z3 \citep{demoura2008z3} solves this with a 10-second timeout. Answer assertion constraints ($\texttt{answer\_a} == \texttt{True}$, weight 1) ensure every candidate receives a nonzero base score, making SICA a strict generalization of SC.
29	
30	\paragraph{Scoring.} Let $\mathcal{C}^{\setminus} = \mathcal{C} \setminus \mathcal{C}^*$. Each candidate $a$ is scored by:
31	\begin{equation}
32	\label{eq:score}
33	\text{score}(a) = \sum_{c \in \mathcal{C}^*} w_c \cdot \sigma(c, a) - \alpha \sum_{c \in \mathcal{C}^{\setminus}} w_c \cdot \sigma(c, a),
34	\end{equation}
35	where $\sigma(c, a) = 1$ if $c$ was extracted from any trace producing answer $a$, and $\alpha = 0.5$. The selected answer is $a^* = \arg\max_{a} \text{score}(a)$.
36	
37	\paragraph{Degeneration condition.} If self-extracted constraints are coupled to their source answer, MAX-SAT retains nearly all ($|\mathcal{C}^{\setminus}| \approx 0$), and scoring degenerates to:
38	\begin{equation}
39	\label{eq:degenerate}
40	\text{score}(a) \approx \sum_{\substack{c \in \mathcal{C}^* \\ \text{source}(c) \to a}} w_c,
41	\end{equation}
42	equivalent to majority voting. We show in \S\ref{sec:confirmation-bias} that this degeneration occurs in practice.
43	
44	\paragraph{The $C_0$ diagnostic.} The multi-candidate rate $C_0 = |\{q : |\mathcal{A}(q)| > 1\}| / |\mathcal{Q}|$ is a zero-cost diagnostic: $C_0 < 5\%$ means SICA reduces to SC. $\alpha = 0.5$ is not critical (${\pm}0.49$\,pp across $\alpha \in [0, 1]$).
45	
46	\paragraph{Bias ratio.} We quantify extraction bias via the \emph{bias ratio}:
47	\begin{equation}\label{eq:mirage}
48	\text{BR}(M,T) = \frac{P(c \text{ supports } a_M \mid a_M \neq a^*)}{P(c \text{ supports } a^* \mid a_M \neq a^*)},
49	\end{equation}
50	where $c$ is a self-extracted constraint, $a_M$ the model's majority answer, and $a^*$ the ground truth. BR quantifies the degree of extraction degeneration under source-attribution scoring (Observation~1): values above 1 reflect the trace-count base rate inherent to source-attributed constraints. $\text{BR} = 1$ indicates no coupling beyond chance. We validate this metric empirically in \S\ref{sec:confirmation-bias}.
51	
52	\subsection{Experimental Setup}
53	\label{sec:exp-setup}
54	
55	\looseness=-1
56	\paragraph{Models.} Qwen2.5-14B-Instruct, Qwen2.5-7B-Instruct, Qwen3-14B (non-thinking mode)~\citep{yang2024qwen25}, Mistral-7B-Instruct-v0.3~\citep{jiang2023mistral}, LLaMA-3.1-8B-Instruct~\citep{dubey2024llama3}, and QwQ-32B~\citep{qwen2024qwq} (7B--32B). We also evaluate the universality of symbolic confirmation bias via cross-model extraction on five frontier models (gpt-4o, gpt-4.1, gpt-5.5, o3, Gemini-2.5-Pro; Table~\ref{tab:frontier-scb}); Mistral-7B extracts constraints from target traces since closed-source APIs do not support self-extraction.
57	
58	\paragraph{Datasets.} FOLIO~\citep{han2022folio} ($n{=}204$, gold logical annotations), ProofWriter depth-5~\citep{tafjord2021proofwriter} ($n{=}600$), LogiQA~\citep{liu2020logiqa} ($n{=}200$), StrategyQA~\citep{geva2021strategyqa} ($n{=}200$). GSM8K ($n{=}30$) and AIME 2024 ($n{=}22$) probe the degenerate regime ($C_0 < 5\%$).
59	
60	\paragraph{Parameters.} $K{=}12$ traces at $T{=}0.7$, extraction at $T_{\text{ext}}{=}0.3$, $\alpha{=}0.5$, Z3 timeout 10s. McNemar exact test ($\alpha{=}0.05$); 95\% bootstrap CIs ($10{,}000$ resamples) for $n \geq 200$. SICA incurs $4.5{\times}$ SC wall-clock; extraction accounts for 76\% of overhead.
61	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "aa14a2d8-6411-4b53-a17d-67e4b45e38b9",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "f13fae6e-93b0-4d0a-bf28-830a9d7df84c",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{SICA Pipeline}\n\\label{sec:pipeline}\n\\label{sec:condorcet}\n\\label{sec:effective-k}\n\nSelf-Consistency (SC) \\citep{wang2023sc} samples $K$ reasoning traces and selects the majority answer. Under correlated traces (Fleiss' $\\kappa$ \\citep{fleiss1971kappa}), effective sample size reduces to\n\\begin{equation}\n\\label{eq:effk}\nK_{\\text{eff}} = K \\,/\\, [1 + (K{-}1) \\cdot \\kappa]\n\\end{equation}\n(following \\citet{ladha1992correlated}). Intuitively, $K_\\text{eff}$ measures how many effectively independent votes $K$ correlated traces contribute; e.g., $K{=}12$ traces with $\\kappa{=}0.69$ yield $K_\\text{eff} \\approx 1.3$, meaning twelve correlated traces carry no more independent information than 1.3 uncorrelated ones. This motivates constraint-based aggregation.\n\nSymbolic Invariant Consensus Aggregation (SICA) extends SC by extracting formal constraints from traces and selecting the answer best supported by the satisfiable subset (Figure~\\ref{fig:pipeline}).\n\n\\paragraph{Trace generation.} Given question $q$, an LLM generates $K$ traces $\\{t_1, \\ldots, t_K\\}$ at temperature $T = 0.7$. Each trace $t_i$ yields answer $a_i$.\n\n\\looseness=-1\n\\paragraph{Constraint extraction.}\\label{sec:constraint-extraction} The same LLM extracts logical constraints from each trace at $T_{\\text{ext}} = 0.3$. The extraction prompt requests JSON output with constraint type, expression, and Z3-compatible formula (Appendix~\\ref{app:prompts}); in practice, 99.0\\% of extracted constraints are propositional at the Z3 level, with only 1.0\\% using true quantifiers. The \\emph{extraction rate} is the fraction of traces yielding at least one parseable constraint.\n\n\\paragraph{Deduplication and MAX-SAT.} Constraints are deduplicated by syntactic equivalence (global average deduplication ratio: 46.0\\%); each unique constraint $c_m$ receives weight $w_m$ equal to the number of source traces. The objective finds the largest-weight satisfiable subset:\n\\begin{equation}\n\\label{eq:maxsat}\n\\mathcal{C}^* = \\arg\\max_{\\mathcal{S} \\subseteq \\mathcal{C}} \\sum_{c \\in \\mathcal{S}} w_c \\quad \\text{s.t.} \\quad \\mathcal{S} \\text{ is satisfiable.}\n\\end{equation}\nZ3 \\citep{demoura2008z3} solves this with a 10-second timeout. Answer assertion constraints ($\\texttt{answer\\_a} == \\texttt{True}$, weight 1) ensure every candidate receives a nonzero base score, making SICA a strict generalization of SC.\n\n\\paragraph{Scoring.} Let $\\mathcal{C}^{\\setminus} = \\mathcal{C} \\setminus \\mathcal{C}^*$. Each candidate $a$ is scored by:\n\\begin{equation}\n\\label{eq:score}\n\\text{score}(a) = \\sum_{c \\in \\mathcal{C}^*} w_c \\cdot \\sigma(c, a) - \\alpha \\sum_{c \\in \\mathcal{C}^{\\setminus}} w_c \\cdot \\sigma(c, a),\n\\end{equation}\nwhere $\\sigma(c, a) = 1$ if $c$ was extracted from any trace producing answer $a$, and $\\alpha = 0.5$. The selected answer is $a^* = \\arg\\max_{a} \\text{score}(a)$.\n\n\\paragraph{Degeneration condition.} If self-extracted constraints are coupled to their source answer, MAX-SAT retains nearly all ($|\\mathcal{C}^{\\setminus}| \\approx 0$), and scoring degenerates to:\n\\begin{equation}\n\\label{eq:degenerate}\n\\text{score}(a) \\approx \\sum_{\\substack{c \\in \\mathcal{C}^* \\\\ \\text{source}(c) \\to a}} w_c,\n\\end{equation}\nequivalent to majority voting. We show in \\S\\ref{sec:confirmation-bias} that this degeneration occurs in practice.\n\n\\paragraph{The $C_0$ diagnostic.} The multi-candidate rate $C_0 = |\\{q : |\\mathcal{A}(q)| > 1\\}| / |\\mathcal{Q}|$ is a zero-cost diagnostic: $C_0 < 5\\%$ means SICA reduces to SC. $\\alpha = 0.5$ is not critical (${\\pm}0.49$\\,pp across $\\alpha \\in [0, 1]$).\n\n\\paragraph{Bias ratio.} We quantify extraction bias via the \\emph{bias ratio}:\n\\begin{equation}\\label{eq:mirage}\n\\text{BR}(M,T) = \\frac{P(c \\text{ supports } a_M \\mid a_M \\neq a^*)}{P(c \\text{ supports } a^* \\mid a_M \\neq a^*)},\n\\end{equation}\nwhere $c$ is a self-extracted constraint, $a_M$ the model's majority answer, and $a^*$ the ground truth. BR quantifies the degree of extraction degeneration under source-attribution scoring (Observation~1): values above 1 reflect the trace-count base rate inherent to source-attributed constraints. $\\text{BR} = 1$ indicates no coupling beyond chance. We validate this metric empirically in \\S\\ref{sec:confirmation-bias}.\n\n\\subsection{Experimental Setup}\n\\label{sec:exp-setup}\n\n\\looseness=-1\n\\paragraph{Models.} Qwen2.5-14B-Instruct, Qwen2.5-7B-Instruct, Qwen3-14B (non-thinking mode)~\\citep{yang2024qwen25}, Mistral-7B-Instruct-v0.3~\\citep{jiang2023mistral}, LLaMA-3.1-8B-Instruct~\\citep{dubey2024llama3}, and QwQ-32B~\\citep{qwen2024qwq} (7B--32B). We also evaluate the universality of symbolic confirmation bias via cross-model extraction on five frontier models (gpt-4o, gpt-4.1, gpt-5.5, o3, Gemini-2.5-Pro; Table~\\ref{tab:frontier-scb}); Mistral-7B extracts constraints from target traces since closed-source APIs do not support self-extraction.\n\n\\paragraph{Datasets.} FOLIO~\\citep{han2022folio} ($n{=}204$, gold logical annotations), ProofWriter depth-5~\\citep{tafjord2021proofwriter} ($n{=}600$), LogiQA~\\citep{liu2020logiqa} ($n{=}200$), StrategyQA~\\citep{geva2021strategyqa} ($n{=}200$). GSM8K ($n{=}30$) and AIME 2024 ($n{=}22$) probe the degenerate regime ($C_0 < 5\\%$).\n\n\\paragraph{Parameters.} $K{=}12$ traces at $T{=}0.7$, extraction at $T_{\\text{ext}}{=}0.3$, $\\alpha{=}0.5$, Z3 timeout 10s. McNemar exact test ($\\alpha{=}0.05$); 95\\% bootstrap CIs ($10{,}000$ resamples) for $n \\geq 200$. SICA incurs $4.5{\\times}$ SC wall-clock; extraction accounts for 76\\% of overhead.\n",
      "numLines": 61,
      "startLine": 1,
      "totalLines": 61
    }
  },
  "sourceToolAssistantUUID": "aa14a2d8-6411-4b53-a17d-67e4b45e38b9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 22 · 2026-05-24T04:28:32.066Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MVx1xCifyBFK21uuhAFb8D`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f13fae6e-93b0-4d0a-bf28-830a9d7df84c",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "7c13d470-240d-4a63-aa77-7022794adcca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-24T04:28:32.072Z_

<details><summary>↩ Tool result · `toolu_01MVx1xCifyBFK21uuhAFb8D`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	\label{sec:main-results}
4	
5	\looseness=-1 Table~\ref{tab:main_results} reports accuracy across all non-degenerate self-extraction conditions sorted by SC baseline. No condition shows a significant SICA effect after FDR control (BH, $m{=}6$ confirmatory conditions; multi-seed aggregates and extensions are exploratory). Two confirmatory conditions show nominally significant degradation: Mistral-7B on ProofWriter ($-2.83$\,pp, raw $p = 0.014$) and Qwen2.5-14B on ProofWriter ($-2.50$\,pp, raw $p = 0.011$); both reach adjusted $p = 0.066$. An aggregate sign test yields 8 positive and 7 negative $\Delta$ values ($p = 1.00$, two-sided). When SICA and SC disagree, SC selects the correct answer $2.6\times$ more often (139 vs.\ 53 across conditions), indicating that constraint-based reweighting introduces noise rather than corrective signal.
6	
7	\begin{table*}[t]
8	\centering
9	\small
10	\caption{SICA vs.\ SC across all non-degenerate self-extraction conditions (sorted by SC). No condition shows a significant gain after BH correction ($m{=}6$ confirmatory; remaining exploratory). $\Delta$ = SICA $-$ SC (pp). Symbols: $^b$gold ICL; \textbf{bold}: $p < 0.05$; {*}\,uncorrected $p < 0.05$ (BH adj.\ $p = 0.066$); $^{3s}$\,3-seed aggregate; $^{4s}$\,4-seed confirmatory aggregate (unmarked: single-seed exploratory; s123/s456/s789 are individual seed runs). All conditions have McNemar power $< 80\%$ for $|\Delta| = 2$\,pp (Appendix~\ref{app:power}). Degenerate conditions ($C_0 < 5\%$: QwQ-32B AIME $n{=}22$, Qwen2.5-14B GSM8K $n{=}30$) yield $\Delta = 0$ and are reported separately in Appendix~\ref{app:oracle}.}
11	\label{tab:main_results}
12	\begin{tabular}{@{}llrrrrl@{}}
13	\toprule
14	Model & Domain & $n$ & SC (\%) & SICA (\%) & $\Delta$ (pp) & $p$ \\
15	\midrule
16	\multicolumn{7}{l}{\textit{Type C: error amplification (SC $\leq$ 40\%)}} \\
17	Mistral-7B & PW-D5 & 600 & 39.33 & 36.50 & $\mathbf{-2.83}$ & 0.014{*} \\
18	\midrule
19	\multicolumn{7}{l}{\textit{Intermediate SC (SC $\sim$50--60\%, Mistral-7B only)}} \\
20	Mistral-7B & LogiQA & 200 & 50.00 & 51.50 & $+$1.50 & 0.581 \\
21	Mistral-7B & FOLIO (s123) & 204 & 54.41 & 57.35 & $+$2.94 & 0.070 \\
22	Mistral-7B$^{3s}$ & FOLIO & 204 & 56.53 & 56.70 & $+$0.16 & 1.000 \\
23	Mistral-7B & FOLIO (s456) & 204 & 55.88 & 55.88 & 0.00 & 1.000 \\
24	Mistral-7B & FOLIO (s789) & 204 & 59.31 & 56.86 & $-$2.45 & 0.267 \\
25	\midrule
26	\multicolumn{7}{l}{\textit{Type A: confirmation bias (SC $\geq$ 60\%)}} \\
27	LLaMA-3.1-8B & FOLIO & 204 & 66.18 & 61.76 & $-$4.41 & 0.093 \\
28	LLaMA-3.1-8B & StrategyQA & 200 & 72.00 & 74.00 & $+$2.00 & 0.424 \\
29	\addlinespace
30	Qwen2.5-14B & FOLIO (ICL)$^b$ & 199 & 74.37 & 74.87 & $+$0.50 & 1.000 \\
31	Qwen2.5-14B & PW-D5 & 600 & 74.00 & 71.50 & $\mathbf{-2.50}$ & 0.011{*} \\
32	Qwen2.5-14B$^{4s}$ & FOLIO & 204 & 75.01 & 73.78 & $-$1.24 & 1.000 \\
33	Qwen2.5-7B & FOLIO & 204 & 75.98 & 76.47 & $+$0.49 & 1.000 \\
34	Qwen2.5-14B & LogiQA & 200 & 79.00 & 78.00 & $-$1.00 & 0.625 \\
35	\addlinespace
36	Qwen3-14B & FOLIO & 204 & 83.33 & 84.80 & $+$1.47 & 1.000 \\
37	Qwen3-14B & PW-D5 & 600 & 85.83 & 85.67 & $-$0.17 & 1.000 \\
38	Qwen3-14B (think) & FOLIO & 204 & 86.27 & 86.76 & $+$0.49 & 1.000 \\
39	\bottomrule
40	\end{tabular}
41	\end{table*}
42	
43	\begin{figure}[t]
44	\centering
45	\includegraphics[width=\columnwidth]{f2_regime_scatter}
46	\caption{SICA $\Delta$ (pp) vs.\ SC baseline. Filled: $n \geq 100$; open: $n < 100$. The intermediate-SC region (50--60\%, shaded) contains the only positive trends (none reaching $p < 0.05$). Type~C: nominally significant degradation (raw $p = 0.014$; BH adj.\ $p = 0.066$).}
47	\label{fig:regime-scatter}
48	\end{figure}
49	
50	\looseness=-1 Figure~\ref{fig:regime-scatter} reveals regime structure. Fleiss' $\kappa$ ranges from 0.21 to 0.82, yielding $K_{\text{eff}} = 1.20\text{--}3.62$ at $K = 12$ (Table~\ref{tab:independence}, Appendix). Three regimes emerge: Type~C (SC $\leq 40\%$), where low accuracy causes error amplification; an intermediate band (50--60\%), containing the only positive trends; and Type~A (SC $\geq 60\%$), where symbolic confirmation bias dominates. Seed-level noise is substantial: across three Mistral-7B seeds, $\Delta$ ranges from $+2.94$ to $-2.45$\,pp despite $\kappa \in [0.41, 0.51]$. We trace the mechanism in \S\ref{sec:analysis}.
51	
52	\looseness=-1 TOST equivalence tests \citep{lakens2017equivalence} with pre-specified margin $\pm 2$\,pp confirm four conditions as equivalent; ten remain underpowered for effects below ${\sim}2$\,pp (MDE 1.86--4.84\,pp; sensitivity analysis in Appendix~\ref{app:power},~\ref{app:tost}). Absence of evidence is not evidence of absence for small effects. Multi-seed replication confirms robustness: mean $\Delta = +0.16 \pm 2.70$\,pp across three Mistral-7B seeds (Table~\ref{tab:multi-seed}); four Qwen2.5-14B seeds yield $\Delta \in [0.00, -2.01]$\,pp. Oracle controls with gold annotations confirm the MAX-SAT mechanism is sound ($+29.90$/$+13.73$\,pp FOLIO, $+17.17$\,pp ProofWriter; $p < 0.001$), yet self-extraction captures only ${\sim}$12\% of this ceiling (Appendix~\ref{app:oracle}).
53	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7c13d470-240d-4a63-aa77-7022794adcca",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "fbf7f2b0-42a7-4947-98a8-3d2819ca5195",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/experiments.tex",
      "content": "\\section{Results}\n\\label{sec:results}\n\\label{sec:main-results}\n\n\\looseness=-1 Table~\\ref{tab:main_results} reports accuracy across all non-degenerate self-extraction conditions sorted by SC baseline. No condition shows a significant SICA effect after FDR control (BH, $m{=}6$ confirmatory conditions; multi-seed aggregates and extensions are exploratory). Two confirmatory conditions show nominally significant degradation: Mistral-7B on ProofWriter ($-2.83$\\,pp, raw $p = 0.014$) and Qwen2.5-14B on ProofWriter ($-2.50$\\,pp, raw $p = 0.011$); both reach adjusted $p = 0.066$. An aggregate sign test yields 8 positive and 7 negative $\\Delta$ values ($p = 1.00$, two-sided). When SICA and SC disagree, SC selects the correct answer $2.6\\times$ more often (139 vs.\\ 53 across conditions), indicating that constraint-based reweighting introduces noise rather than corrective signal.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{SICA vs.\\ SC across all non-degenerate self-extraction conditions (sorted by SC). No condition shows a significant gain after BH correction ($m{=}6$ confirmatory; remaining exploratory). $\\Delta$ = SICA $-$ SC (pp). Symbols: $^b$gold ICL; \\textbf{bold}: $p < 0.05$; {*}\\,uncorrected $p < 0.05$ (BH adj.\\ $p = 0.066$); $^{3s}$\\,3-seed aggregate; $^{4s}$\\,4-seed confirmatory aggregate (unmarked: single-seed exploratory; s123/s456/s789 are individual seed runs). All conditions have McNemar power $< 80\\%$ for $|\\Delta| = 2$\\,pp (Appendix~\\ref{app:power}). Degenerate conditions ($C_0 < 5\\%$: QwQ-32B AIME $n{=}22$, Qwen2.5-14B GSM8K $n{=}30$) yield $\\Delta = 0$ and are reported separately in Appendix~\\ref{app:oracle}.}\n\\label{tab:main_results}\n\\begin{tabular}{@{}llrrrrl@{}}\n\\toprule\nModel & Domain & $n$ & SC (\\%) & SICA (\\%) & $\\Delta$ (pp) & $p$ \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Type C: error amplification (SC $\\leq$ 40\\%)}} \\\\\nMistral-7B & PW-D5 & 600 & 39.33 & 36.50 & $\\mathbf{-2.83}$ & 0.014{*} \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Intermediate SC (SC $\\sim$50--60\\%, Mistral-7B only)}} \\\\\nMistral-7B & LogiQA & 200 & 50.00 & 51.50 & $+$1.50 & 0.581 \\\\\nMistral-7B & FOLIO (s123) & 204 & 54.41 & 57.35 & $+$2.94 & 0.070 \\\\\nMistral-7B$^{3s}$ & FOLIO & 204 & 56.53 & 56.70 & $+$0.16 & 1.000 \\\\\nMistral-7B & FOLIO (s456) & 204 & 55.88 & 55.88 & 0.00 & 1.000 \\\\\nMistral-7B & FOLIO (s789) & 204 & 59.31 & 56.86 & $-$2.45 & 0.267 \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Type A: confirmation bias (SC $\\geq$ 60\\%)}} \\\\\nLLaMA-3.1-8B & FOLIO & 204 & 66.18 & 61.76 & $-$4.41 & 0.093 \\\\\nLLaMA-3.1-8B & StrategyQA & 200 & 72.00 & 74.00 & $+$2.00 & 0.424 \\\\\n\\addlinespace\nQwen2.5-14B & FOLIO (ICL)$^b$ & 199 & 74.37 & 74.87 & $+$0.50 & 1.000 \\\\\nQwen2.5-14B & PW-D5 & 600 & 74.00 & 71.50 & $\\mathbf{-2.50}$ & 0.011{*} \\\\\nQwen2.5-14B$^{4s}$ & FOLIO & 204 & 75.01 & 73.78 & $-$1.24 & 1.000 \\\\\nQwen2.5-7B & FOLIO & 204 & 75.98 & 76.47 & $+$0.49 & 1.000 \\\\\nQwen2.5-14B & LogiQA & 200 & 79.00 & 78.00 & $-$1.00 & 0.625 \\\\\n\\addlinespace\nQwen3-14B & FOLIO & 204 & 83.33 & 84.80 & $+$1.47 & 1.000 \\\\\nQwen3-14B & PW-D5 & 600 & 85.83 & 85.67 & $-$0.17 & 1.000 \\\\\nQwen3-14B (think) & FOLIO & 204 & 86.27 & 86.76 & $+$0.49 & 1.000 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{f2_regime_scatter}\n\\caption{SICA $\\Delta$ (pp) vs.\\ SC baseline. Filled: $n \\geq 100$; open: $n < 100$. The intermediate-SC region (50--60\\%, shaded) contains the only positive trends (none reaching $p < 0.05$). Type~C: nominally significant degradation (raw $p = 0.014$; BH adj.\\ $p = 0.066$).}\n\\label{fig:regime-scatter}\n\\end{figure}\n\n\\looseness=-1 Figure~\\ref{fig:regime-scatter} reveals regime structure. Fleiss' $\\kappa$ ranges from 0.21 to 0.82, yielding $K_{\\text{eff}} = 1.20\\text{--}3.62$ at $K = 12$ (Table~\\ref{tab:independence}, Appendix). Three regimes emerge: Type~C (SC $\\leq 40\\%$), where low accuracy causes error amplification; an intermediate band (50--60\\%), containing the only positive trends; and Type~A (SC $\\geq 60\\%$), where symbolic confirmation bias dominates. Seed-level noise is substantial: across three Mistral-7B seeds, $\\Delta$ ranges from $+2.94$ to $-2.45$\\,pp despite $\\kappa \\in [0.41, 0.51]$. We trace the mechanism in \\S\\ref{sec:analysis}.\n\n\\looseness=-1 TOST equivalence tests \\citep{lakens2017equivalence} with pre-specified margin $\\pm 2$\\,pp confirm four conditions as equivalent; ten remain underpowered for effects below ${\\sim}2$\\,pp (MDE 1.86--4.84\\,pp; sensitivity analysis in Appendix~\\ref{app:power},~\\ref{app:tost}). Absence of evidence is not evidence of absence for small effects. Multi-seed replication confirms robustness: mean $\\Delta = +0.16 \\pm 2.70$\\,pp across three Mistral-7B seeds (Table~\\ref{tab:multi-seed}); four Qwen2.5-14B seeds yield $\\Delta \\in [0.00, -2.01]$\\,pp. Oracle controls with gold annotations confirm the MAX-SAT mechanism is sound ($+29.90$/$+13.73$\\,pp FOLIO, $+17.17$\\,pp ProofWriter; $p < 0.001$), yet self-extraction captures only ${\\sim}$12\\% of this ceiling (Appendix~\\ref{app:oracle}).\n",
      "numLines": 53,
      "startLine": 1,
      "totalLines": 53
    }
  },
  "sourceToolAssistantUUID": "7c13d470-240d-4a63-aa77-7022794adcca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 24 · 2026-05-24T04:28:32.553Z_

<details open><summary>🔧 Tool call — Read · `toolu_0131kjLE6DbKXBcoDShArdGB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fbf7f2b0-42a7-4947-98a8-3d2819ca5195",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "11af70ea-2fee-4e50-9de7-1c965907998c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 25 · 2026-05-24T04:28:32.559Z_

<details><summary>↩ Tool result · `toolu_0131kjLE6DbKXBcoDShArdGB`</summary>

```text
1	\section{The Symbolic Mirage}
2	\label{sec:analysis}
3	
4	\subsection{Symbolic Confirmation Bias}
5	\label{sec:confirmation-bias}
6	
7	\looseness=-1 Self-extracted constraints systematically align with the model's majority answer---a persistent empirical property of zero-shot self-extraction pipelines, not a cognitive bias analogy. On Mistral-7B FOLIO, when SICA errs, 83.3\% of constraints support the incorrect answer---bias ratio $4.97\times$ (Table~\ref{tab:cross-model-bias})---and 94\% of errors overlap with SC. Z3 rejects only 3.4\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on $\geq$99\% of problems across all weight settings $\alpha$ (Table~\ref{tab:alpha-ablation}), confirming that the formal verification layer is vacuous (Eq.~\ref{eq:degenerate}): 99\% of constraints pass Z3 validation yet add no information beyond majority voting.
8	
9	\looseness=-1 Crucially, BR $> 1$ is not an independent finding but a corollary of the degeneration identified in Observation~1: under source-attribution scoring, constraint weight is proportional to trace count, so the majority answer necessarily receives more support. A permutation null model---randomizing constraint--answer associations while preserving per-trace counts (1{,}000 permutations)---confirms this: $\text{BR}_\text{null} \approx \text{BR}_\text{obs}$ ($\text{BR}_\text{excess} \approx 0$; $p > 0.7$) across all tested conditions. BR thus quantifies the degree of extraction degeneration---how completely constraints collapse to majority-vote equivalents---not an independent bias signal. On problems where SC is correct, constraints still track the majority ($\text{BR}_\text{correct}$ $1.29$--$3.64\times$), confirming that self-extracted constraints reflect distributional frequency rather than logical validity.
10	
11	\looseness=-1 The pattern generalizes across nine models from 7B to frontier (BR $1.66$--$4.97\times$; Table~\ref{tab:frontier-scb}) and all eight cells of a $2{\times}2$ generator${\times}$extractor matrix (range $1.94$--$2.70$; Appendix~\ref{app:2x2}). Constraints use trace-specific variables (56.4\% zero variable overlap across answer groups), collapsing aggregation to majority voting.
12	
13	\begin{table}[t]
14	\centering
15	\small
16	\setlength{\tabcolsep}{3pt}
17	\caption{Symbolic confirmation bias across nine models on FOLIO ($n = 204$). BR: mean per-problem bias ratio. $n_\text{err}$: number of incorrect instances on which BR is computed. $\Delta$: SICA $-$ SC (pp). Ext.: $^a$self-extraction; $^b$cross-model (Mistral-7B extracts FOL from target traces). $^*$Interim ($n = 95/204$). $^\dagger$8 API-failure questions excluded ($n = 196$). All models exhibit $\text{BR} > 1$; BR estimates for high-accuracy models ($n_\text{err} < 40$) have wider confidence intervals; Gemini ($n_\text{err} \approx 12$) should be interpreted with particular caution. Process-level similarity ($\kappa_{\text{proc}}$) ranges from $0.25$ (R1-Distill) to $0.79$ (gpt-4o/4.1/Gemini); see Table~\ref{tab:cross-model-process}.}
18	\label{tab:frontier-scb}
19	\resizebox{\columnwidth}{!}{\begin{tabular}{@{}llrrrrl@{}}
20	\toprule
21	Model & Ext. & SC (\%) & $n_\text{err}$ & BR & $\Delta$ (pp) \\
22	\midrule
23	Mistral-7B & $^a$ & 55.88 & 90 & 4.97 & 0.00 \\
24	LLaMA-8B & $^a$ & \textrm{---} & \textrm{---} & 2.88 & \textrm{---} \\
25	Qwen-14B & $^a$ & 75.98 & 49 & 3.85 & $-$0.49 \\
26	\addlinespace
27	R1-Distill-8B & $^b$ & 74.51 & 52 & 2.92 & $+$2.45 \\
28	gpt-4o & $^a$ & 76.96 & 47 & 2.65 & $-$1.96 \\
29	gpt-4.1 & $^b$ & 82.84 & 35 & 2.70 & $-$1.47 \\
30	gpt-5.5 & $^b$ & 84.31 & 32 & 3.48 & $+$0.49 \\
31	o3$^\dagger$ & $^b$ & 82.65 & 34 & 1.66 & 0.00 \\
32	Gemini-2.5-Pro$^*$ & $^b$ & 87.37 & 12 & 2.79 & $-$1.05 \\
33	\bottomrule
34	\end{tabular}}
35	\end{table}
36	
37	\looseness=-1 Two controls rule out answer leakage: BR is uniform across reasoning steps (Fisher $p = 0.71$), and removing answer sentences before extraction yields no BR decrease (Wilcoxon $p \geq 0.12$) despite accuracy loss (McNemar $p < 0.013$). The bias reflects a distributional prior embedded throughout reasoning, not answer contamination.
38	
39	\label{sec:process-kappa}
40	\looseness=-1 Reasoning-process overlap exceeds answer-level correlation: mean process similarity (pairwise TF-IDF cosine) reaches 0.69 on Mistral-7B FOLIO, far exceeding answer-level $\kappa$ ($0.41$--$0.51$). The gap generalizes across four families (Table~\ref{tab:cross-model-process}). Under cross-model extraction, SICA gain decreases monotonically with process similarity ($\rho = -1.0$, $p = 0.008$; Table~\ref{tab:process-gradient}; conditional correction analysis in Appendix~\ref{app:cil}).
41	
42	\looseness=-1 These patterns---universal BR $> 1$, structural equivalence to trace-count distributions, and process-level correlation exceeding answer-level agreement---follow from a persistent empirical property of zero-shot self-extraction pipelines.
43	
44	\smallskip\noindent
45	\textbf{Observation 1} \textit{(Argmax Preservation).}\;%
46	Let $t_1, \ldots, t_K \overset{\mathrm{i.i.d.}}{\sim} P_M(\cdot \mid q)$ with trace-determined answers $a_i = h(t_i)$ and $n_a = |\{i : a_i = a\}|$.
47	Under (i)~the degeneration condition $|\mathcal{C}^{\setminus}| \approx 0$ (Eq.~\ref{eq:degenerate}), (ii)~source-attribution scoring where $\sigma(c,a) {=} 1$ iff $c$ originates from a trace producing $a$ (Eq.~\ref{eq:score}), and (iii)~approximately uniform constraint yield per trace within each answer group, SICA reduces to majority vote: $\arg\max_a \operatorname{score}(a) = \arg\max_a n_a$.
48	
49	\smallskip\noindent
50	\textit{Empirical support.}\;%
51	The degeneration condition is quantified by the Z3 rejection rate: $|\mathcal{C}^{\setminus}|/|\mathcal{C}| \approx 0.034$, confirming $|\mathcal{C}^{\setminus}| \approx 0$. Source-attribution restricts each constraint's contribution to its originating answer. For condition~(iii), per-trace constraint yield averages $5.6$--$6.0$ constraints across answer groups (median within-problem CV${=}0.26$; Appendix~\ref{app:constraint-quality}), making total weight approximately proportional to $n_a$. SICA and majority vote select the same answer on 96.1\% of problems for Qwen2.5-14B ($n{=}804$; Table~\ref{tab:ablation}) and over 90\% across all tested conditions. Varying constraint weight $\alpha$ across $[0,1]$---from pure Z3 satisfiability ($\alpha{=}0$, no source-attribution) to full source-attribution ($\alpha{=}1$)---preserves ${\geq}99\%$ agreement (Table~\ref{tab:alpha-ablation}), confirming that the equivalence is driven by degeneration rather than the specific weighting scheme.
52	
53	\smallskip\noindent
54	\textit{Per-trace separation analysis.}\;%
55	Across 81\% of problems with non-unanimous votes (Mistral-7B, FOLIO), per-trace constraint density is balanced between majority and minority answer groups ($6.0$ vs.\ $5.9$ constraints/trace) and MAX-SAT exclusion rates are comparable ($0.185$ vs.\ $0.172$): the extraction itself is unbiased. Volume amplification is ${\approx}1.0\times$---the constraint layer neither inflates nor dampens the CoT vote ratio. Yet source-attribution binds each constraint to its originating trace's answer: 92.2\% of non-unanimous problems contain cross-group shared formulas that contribute to each answer group in proportion to its trace count, providing no discriminative signal. On 82.4\% of problems where the minority vote is correct, SICA still follows the majority (correction rate 17.6\%). SCB is thus not an independent bias introduced by extraction but a transparency property of the pipeline: source-attribution scoring is informationally transparent to the CoT trace distribution, preserving rather than correcting the majority-vote structure.
56	
57	\looseness=-1 By the data processing inequality \citep{cover2006elements}, $I(C_{1:K};\, Y) \leq I(T_{1:K};\, Y)$ for any deterministic extraction $f$. The contribution is not this standard bound but the identification of the $M{\to}T{\to}A{\to}C$ Markov chain structure in self-extraction pipelines: under the degeneration condition of Observation~1 ($|\mathcal{C}^{\setminus}| \approx 0$), constraints are fully determined by answers, yielding the tighter bound $I(C;\, Y) \leq I(A;\, Y)$ and the approximate conditional independence $C \approx\!\!\perp Y \mid A$ (Figure~\ref{fig:causal-dag}). This is a necessary condition, not a sufficient explanation; the empirical findings (Observation~1, BR, degeneration condition) provide the sufficient evidence.
58	
59	\smallskip\noindent
60	\textbf{Remark.}\;%
61	Observation~1 assumes degeneration and source attribution. Under \emph{semantic} evaluation, the equivalence additionally requires \emph{answer alignment}: $P(c_i \text{ supports } a_i) \geq P(c_i \text{ supports } a')$ for $a' \neq a_i$, which is structurally motivated and empirically validated ($\mathrm{BR} \in [1.66,\, 4.97]$; Table~\ref{tab:frontier-scb}), but could fail if $f$ systematically extracted premises contradicting their source trace's conclusion.
62	Since Observation~1 shows SICA reduces to majority vote under degeneration, $\mathrm{BR} \geq 1$ follows from the trace-count geometry; the empirical BR consistently exceeds this floor ($1.66\times$--$4.97\times$; Table~\ref{tab:frontier-scb}), reflecting both base-rate effects and extraction alignment.
63	
64	\begin{figure}[t]
65	\centering
66	\begin{tikzpicture}[
67	  node distance=0.8cm,
68	  nd/.style={rectangle, rounded corners=2pt, draw=black!50,
69	             fill=gray!6, minimum height=5.5mm, minimum width=8mm,
70	             font=\small},
71	  bn/.style={nd, fill=red!10, draw=red!50, line width=0.7pt},
72	  ex/.style={nd, draw=gray!50, densely dashed, fill=white},
73	  >=Stealth,
74	  base/.style={->, semithick, black!50},
75	  leak/.style={->, line width=0.85pt, red!50},
76	  sub/.style={font=\scriptsize, text=gray!55},
77	]
78	\node[nd]             (M) {$M$};
79	\node[nd, right=of M] (T) {$T$};
80	\node[bn, right=of T] (A) {$A$};
81	\node[nd, right=of A] (C) {$C$};
82	\node[nd, right=of C] (S) {$S$};
83	\node[ex, above=0.65cm of A] (Y) {$Y$};
84	
85	\node[sub, below=0.5mm of M] {Model};
86	\node[sub, below=0.5mm of T] {Trace};
87	\node[sub, below=0.5mm of A] {Answer};
88	\node[sub, below=0.5mm of C] {Constr.};
89	\node[sub, below=0.5mm of S] {SICA};
90	\node[sub, above=0.5mm of Y] {Truth};
91	
92	\draw[base] (M) -- (T);
93	\draw[leak] (T) -- (A);
94	\draw[leak] (A) -- (C);
95	\draw[base] (C) -- (S);
96	\draw[base, bend right=22] (T) to (C);
97	
98	\draw[densely dashed, gray!30, shorten >=1pt, shorten <=1pt] (Y) -- (A);
99	
100	\node[font=\tiny, text=red!45, fill=white, inner sep=0.5pt]
101	  at ($(A)!0.5!(C) + (0, 0.27)$) {\textit{bottleneck}};
102	
103	\node[draw=gray!30, rounded corners=1.5pt, fill=white,
104	      inner sep=2.5pt, font=\scriptsize, text=gray!50,
105	      right=0.2cm of Y]
106	  {$C \approx\!\!\perp Y \mid A$};
107	\end{tikzpicture}
108	\caption{Causal DAG of the self-extraction pipeline. All information about ground truth $Y$ reaching constraints $C$ is mediated by answer $A$. Approximate conditional independence ($C \approx\!\!\perp Y \mid A$) is empirically supported by ${>}90\%$ argmax agreement (Observation~1) but is not a formal consequence of the DPI bound.}
109	\label{fig:causal-dag}
110	\end{figure}
111	
112	\looseness=-1 Since the bias holds across all tested models, tasks, and extraction functions, training-free remediation strategies face a structural limitation: methods that preserve extraction accuracy necessarily inherit the model's distributional prior. This regularity holds across all 27 tested zero-shot template extraction strategies; whether few-shot or iterative refinement approaches alter this pattern remains open.
113	
114	\subsection{Why Remediation Fails}
115	\label{sec:remediation}
116	\label{sec:interventions}
117	
118	\looseness=-1 All 27 training-free variants within the constraint-extraction paradigm, spanning four categories, produce neutral-to-negative results (Figure~\ref{fig:interventions-summary}; Appendices~\ref{app:extraction}--\ref{app:entropy}). The pattern reveals a persistent independence-accuracy trade-off. \emph{Diversity-seeking strategies} (temperature variation, persona sampling) shift $K_\text{eff}$ by $< 0.5$---insufficient to break correlation. \emph{Constraint-level interventions} (explicit negation, contrastive prompting) leave the Z3 rejection rate at ${\sim}3.4\%$---degeneration persists. \emph{Debate} ($\kappa = 0.15$, $\Delta = -18.6$\,pp) breaks correlation but collapses accuracy; \emph{cross-model extraction} leaves $\kappa$ near the same-model ceiling ($\kappa \approx 0.40$--$0.47$). No individual strategy achieves significance after correction (Appendix~\ref{app:intervention-individual}). Across three model families, self-extraction cannot produce constraints independent of the distributional prior.
119	
120	\begin{figure}[t]
121	\centering
122	\includegraphics[width=\columnwidth]{figures/fig2_interventions_compact.pdf}
123	\caption{Twenty-three of 27 training-free strategies across four categories (four additional strategies tested but omitted for clarity). All produce neutral-to-negative $\Delta$ vs.\ SC. Grey band: $\pm 1$\,pp noise zone.}
124	\label{fig:interventions-summary}
125	\end{figure}
126	
127	\subsection{Diagnostic Framework}
128	\label{sec:diagnostic-framework}
129	\label{sec:diagnostics}
130	
131	\looseness=-1 Three zero-cost diagnostics predict the outcome of any self-extraction-based aggregation method from a $K = 12$ pilot run: (1) the degenerate-regime indicator $C_0 < 5\%$ (SICA reduces to SC); (2) the diversity floor $K_\text{eff} \leq 1.30$ (insufficient vote diversity for any aggregation gain); (3) the bias ratio BR combined with SC regime (Type~A: SC $\geq 60\%$ with BR $> 1$ predicts confirmation-bias degradation; Type~C: SC $\leq 40\%$ predicts error amplification). These boundaries correctly characterize the failure mode across all 60 tested conditions (16 main configurations, 27 remediation variants on Mistral-7B${\times}$FOLIO, and 17 analytical conditions) within the self-extraction paradigm. The framework's practical value lies in failure-mode diagnosis---degenerate, diversity-limited, or confirmation-biased---from a $K{=}12$ pilot run, enabling practitioners to rule out self-extraction before full deployment. Conversely, when diagnostics detect sufficient capability gap (\S\ref{sec:cross-arch}), the framework correctly predicts positive gain ($+6.67$\,pp for Mistral-7B on ProofWriter).
132	
133	\looseness=-1 Decision boundaries ($C_0 < 5\%$, $K_\text{eff} \leq 1.30$, SC $< 40\%$) were derived from Mistral-7B and Qwen2.5-14B. We evaluate prospectively on two held-out generators: LLaMA-3.1-8B (different family) on FOLIO, where the framework predicts Type~A bias and the observed $\Delta = -4.41$\,pp confirms; and Qwen3-14B (same family, different generation) on FOLIO and ProofWriter, likewise confirmed ($\Delta \leq +1.47$\,pp, n.s.).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "11af70ea-2fee-4e50-9de7-1c965907998c",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "390c5483-622f-499d-8ab7-280d1d848de1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
      "content": "\\section{The Symbolic Mirage}\n\\label{sec:analysis}\n\n\\subsection{Symbolic Confirmation Bias}\n\\label{sec:confirmation-bias}\n\n\\looseness=-1 Self-extracted constraints systematically align with the model's majority answer---a persistent empirical property of zero-shot self-extraction pipelines, not a cognitive bias analogy. On Mistral-7B FOLIO, when SICA errs, 83.3\\% of constraints support the incorrect answer---bias ratio $4.97\\times$ (Table~\\ref{tab:cross-model-bias})---and 94\\% of errors overlap with SC. Z3 rejects only 3.4\\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on $\\geq$99\\% of problems across all weight settings $\\alpha$ (Table~\\ref{tab:alpha-ablation}), confirming that the formal verification layer is vacuous (Eq.~\\ref{eq:degenerate}): 99\\% of constraints pass Z3 validation yet add no information beyond majority voting.\n\n\\looseness=-1 Crucially, BR $> 1$ is not an independent finding but a corollary of the degeneration identified in Observation~1: under source-attribution scoring, constraint weight is proportional to trace count, so the majority answer necessarily receives more support. A permutation null model---randomizing constraint--answer associations while preserving per-trace counts (1{,}000 permutations)---confirms this: $\\text{BR}_\\text{null} \\approx \\text{BR}_\\text{obs}$ ($\\text{BR}_\\text{excess} \\approx 0$; $p > 0.7$) across all tested conditions. BR thus quantifies the degree of extraction degeneration---how completely constraints collapse to majority-vote equivalents---not an independent bias signal. On problems where SC is correct, constraints still track the majority ($\\text{BR}_\\text{correct}$ $1.29$--$3.64\\times$), confirming that self-extracted constraints reflect distributional frequency rather than logical validity.\n\n\\looseness=-1 The pattern generalizes across nine models from 7B to frontier (BR $1.66$--$4.97\\times$; Table~\\ref{tab:frontier-scb}) and all eight cells of a $2{\\times}2$ generator${\\times}$extractor matrix (range $1.94$--$2.70$; Appendix~\\ref{app:2x2}). Constraints use trace-specific variables (56.4\\% zero variable overlap across answer groups), collapsing aggregation to majority voting.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\caption{Symbolic confirmation bias across nine models on FOLIO ($n = 204$). BR: mean per-problem bias ratio. $n_\\text{err}$: number of incorrect instances on which BR is computed. $\\Delta$: SICA $-$ SC (pp). Ext.: $^a$self-extraction; $^b$cross-model (Mistral-7B extracts FOL from target traces). $^*$Interim ($n = 95/204$). $^\\dagger$8 API-failure questions excluded ($n = 196$). All models exhibit $\\text{BR} > 1$; BR estimates for high-accuracy models ($n_\\text{err} < 40$) have wider confidence intervals; Gemini ($n_\\text{err} \\approx 12$) should be interpreted with particular caution. Process-level similarity ($\\kappa_{\\text{proc}}$) ranges from $0.25$ (R1-Distill) to $0.79$ (gpt-4o/4.1/Gemini); see Table~\\ref{tab:cross-model-process}.}\n\\label{tab:frontier-scb}\n\\resizebox{\\columnwidth}{!}{\\begin{tabular}{@{}llrrrrl@{}}\n\\toprule\nModel & Ext. & SC (\\%) & $n_\\text{err}$ & BR & $\\Delta$ (pp) \\\\\n\\midrule\nMistral-7B & $^a$ & 55.88 & 90 & 4.97 & 0.00 \\\\\nLLaMA-8B & $^a$ & \\textrm{---} & \\textrm{---} & 2.88 & \\textrm{---} \\\\\nQwen-14B & $^a$ & 75.98 & 49 & 3.85 & $-$0.49 \\\\\n\\addlinespace\nR1-Distill-8B & $^b$ & 74.51 & 52 & 2.92 & $+$2.45 \\\\\ngpt-4o & $^a$ & 76.96 & 47 & 2.65 & $-$1.96 \\\\\ngpt-4.1 & $^b$ & 82.84 & 35 & 2.70 & $-$1.47 \\\\\ngpt-5.5 & $^b$ & 84.31 & 32 & 3.48 & $+$0.49 \\\\\no3$^\\dagger$ & $^b$ & 82.65 & 34 & 1.66 & 0.00 \\\\\nGemini-2.5-Pro$^*$ & $^b$ & 87.37 & 12 & 2.79 & $-$1.05 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\looseness=-1 Two controls rule out answer leakage: BR is uniform across reasoning steps (Fisher $p = 0.71$), and removing answer sentences before extraction yields no BR decrease (Wilcoxon $p \\geq 0.12$) despite accuracy loss (McNemar $p < 0.013$). The bias reflects a distributional prior embedded throughout reasoning, not answer contamination.\n\n\\label{sec:process-kappa}\n\\looseness=-1 Reasoning-process overlap exceeds answer-level correlation: mean process similarity (pairwise TF-IDF cosine) reaches 0.69 on Mistral-7B FOLIO, far exceeding answer-level $\\kappa$ ($0.41$--$0.51$). The gap generalizes across four families (Table~\\ref{tab:cross-model-process}). Under cross-model extraction, SICA gain decreases monotonically with process similarity ($\\rho = -1.0$, $p = 0.008$; Table~\\ref{tab:process-gradient}; conditional correction analysis in Appendix~\\ref{app:cil}).\n\n\\looseness=-1 These patterns---universal BR $> 1$, structural equivalence to trace-count distributions, and process-level correlation exceeding answer-level agreement---follow from a persistent empirical property of zero-shot self-extraction pipelines.\n\n\\smallskip\\noindent\n\\textbf{Observation 1} \\textit{(Argmax Preservation).}\\;%\nLet $t_1, \\ldots, t_K \\overset{\\mathrm{i.i.d.}}{\\sim} P_M(\\cdot \\mid q)$ with trace-determined answers $a_i = h(t_i)$ and $n_a = |\\{i : a_i = a\\}|$.\nUnder (i)~the degeneration condition $|\\mathcal{C}^{\\setminus}| \\approx 0$ (Eq.~\\ref{eq:degenerate}), (ii)~source-attribution scoring where $\\sigma(c,a) {=} 1$ iff $c$ originates from a trace producing $a$ (Eq.~\\ref{eq:score}), and (iii)~approximately uniform constraint yield per trace within each answer group, SICA reduces to majority vote: $\\arg\\max_a \\operatorname{score}(a) = \\arg\\max_a n_a$.\n\n\\smallskip\\noindent\n\\textit{Empirical support.}\\;%\nThe degeneration condition is quantified by the Z3 rejection rate: $|\\mathcal{C}^{\\setminus}|/|\\mathcal{C}| \\approx 0.034$, confirming $|\\mathcal{C}^{\\setminus}| \\approx 0$. Source-attribution restricts each constraint's contribution to its originating answer. For condition~(iii), per-trace constraint yield averages $5.6$--$6.0$ constraints across answer groups (median within-problem CV${=}0.26$; Appendix~\\ref{app:constraint-quality}), making total weight approximately proportional to $n_a$. SICA and majority vote select the same answer on 96.1\\% of problems for Qwen2.5-14B ($n{=}804$; Table~\\ref{tab:ablation}) and over 90\\% across all tested conditions. Varying constraint weight $\\alpha$ across $[0,1]$---from pure Z3 satisfiability ($\\alpha{=}0$, no source-attribution) to full source-attribution ($\\alpha{=}1$)---preserves ${\\geq}99\\%$ agreement (Table~\\ref{tab:alpha-ablation}), confirming that the equivalence is driven by degeneration rather than the specific weighting scheme.\n\n\\smallskip\\noindent\n\\textit{Per-trace separation analysis.}\\;%\nAcross 81\\% of problems with non-unanimous votes (Mistral-7B, FOLIO), per-trace constraint density is balanced between majority and minority answer groups ($6.0$ vs.\\ $5.9$ constraints/trace) and MAX-SAT exclusion rates are comparable ($0.185$ vs.\\ $0.172$): the extraction itself is unbiased. Volume amplification is ${\\approx}1.0\\times$---the constraint layer neither inflates nor dampens the CoT vote ratio. Yet source-attribution binds each constraint to its originating trace's answer: 92.2\\% of non-unanimous problems contain cross-group shared formulas that contribute to each answer group in proportion to its trace count, providing no discriminative signal. On 82.4\\% of problems where the minority vote is correct, SICA still follows the majority (correction rate 17.6\\%). SCB is thus not an independent bias introduced by extraction but a transparency property of the pipeline: source-attribution scoring is informationally transparent to the CoT trace distribution, preserving rather than correcting the majority-vote structure.\n\n\\looseness=-1 By the data processing inequality \\citep{cover2006elements}, $I(C_{1:K};\\, Y) \\leq I(T_{1:K};\\, Y)$ for any deterministic extraction $f$. The contribution is not this standard bound but the identification of the $M{\\to}T{\\to}A{\\to}C$ Markov chain structure in self-extraction pipelines: under the degeneration condition of Observation~1 ($|\\mathcal{C}^{\\setminus}| \\approx 0$), constraints are fully determined by answers, yielding the tighter bound $I(C;\\, Y) \\leq I(A;\\, Y)$ and the approximate conditional independence $C \\approx\\!\\!\\perp Y \\mid A$ (Figure~\\ref{fig:causal-dag}). This is a necessary condition, not a sufficient explanation; the empirical findings (Observation~1, BR, degeneration condition) provide the sufficient evidence.\n\n\\smallskip\\noindent\n\\textbf{Remark.}\\;%\nObservation~1 assumes degeneration and source attribution. Under \\emph{semantic} evaluation, the equivalence additionally requires \\emph{answer alignment}: $P(c_i \\text{ supports } a_i) \\geq P(c_i \\text{ supports } a')$ for $a' \\neq a_i$, which is structurally motivated and empirically validated ($\\mathrm{BR} \\in [1.66,\\, 4.97]$; Table~\\ref{tab:frontier-scb}), but could fail if $f$ systematically extracted premises contradicting their source trace's conclusion.\nSince Observation~1 shows SICA reduces to majority vote under degeneration, $\\mathrm{BR} \\geq 1$ follows from the trace-count geometry; the empirical BR consistently exceeds this floor ($1.66\\times$--$4.97\\times$; Table~\\ref{tab:frontier-scb}), reflecting both base-rate effects and extraction alignment.\n\n\\begin{figure}[t]\n\\centering\n\\begin{tikzpicture}[\n  node distance=0.8cm,\n  nd/.style={rectangle, rounded corners=2pt, draw=black!50,\n             fill=gray!6, minimum height=5.5mm, minimum width=8mm,\n             font=\\small},\n  bn/.style={nd, fill=red!10, draw=red!50, line width=0.7pt},\n  ex/.style={nd, draw=gray!50, densely dashed, fill=white},\n  >=Stealth,\n  base/.style={->, semithick, black!50},\n  leak/.style={->, line width=0.85pt, red!50},\n  sub/.style={font=\\scriptsize, text=gray!55},\n]\n\\node[nd]             (M) {$M$};\n\\node[nd, right=of M] (T) {$T$};\n\\node[bn, right=of T] (A) {$A$};\n\\node[nd, right=of A] (C) {$C$};\n\\node[nd, right=of C] (S) {$S$};\n\\node[ex, above=0.65cm of A] (Y) {$Y$};\n\n\\node[sub, below=0.5mm of M] {Model};\n\\node[sub, below=0.5mm of T] {Trace};\n\\node[sub, below=0.5mm of A] {Answer};\n\\node[sub, below=0.5mm of C] {Constr.};\n\\node[sub, below=0.5mm of S] {SICA};\n\\node[sub, above=0.5mm of Y] {Truth};\n\n\\draw[base] (M) -- (T);\n\\draw[leak] (T) -- (A);\n\\draw[leak] (A) -- (C);\n\\draw[base] (C) -- (S);\n\\draw[base, bend right=22] (T) to (C);\n\n\\draw[densely dashed, gray!30, shorten >=1pt, shorten <=1pt] (Y) -- (A);\n\n\\node[font=\\tiny, text=red!45, fill=white, inner sep=0.5pt]\n  at ($(A)!0.5!(C) + (0, 0.27)$) {\\textit{bottleneck}};\n\n\\node[draw=gray!30, rounded corners=1.5pt, fill=white,\n      inner sep=2.5pt, font=\\scriptsize, text=gray!50,\n      right=0.2cm of Y]\n  {$C \\approx\\!\\!\\perp Y \\mid A$};\n\\end{tikzpicture}\n\\caption{Causal DAG of the self-extraction pipeline. All information about ground truth $Y$ reaching constraints $C$ is mediated by answer $A$. Approximate conditional independence ($C \\approx\\!\\!\\perp Y \\mid A$) is empirically supported by ${>}90\\%$ argmax agreement (Observation~1) but is not a formal consequence of the DPI bound.}\n\\label{fig:causal-dag}\n\\end{figure}\n\n\\looseness=-1 Since the bias holds across all tested models, tasks, and extraction functions, training-free remediation strategies face a structural limitation: methods that preserve extraction accuracy necessarily inherit the model's distributional prior. This regularity holds across all 27 tested zero-shot template extraction strategies; whether few-shot or iterative refinement approaches alter this pattern remains open.\n\n\\subsection{Why Remediation Fails}\n\\label{sec:remediation}\n\\label{sec:interventions}\n\n\\looseness=-1 All 27 training-free variants within the constraint-extraction paradigm, spanning four categories, produce neutral-to-negative results (Figure~\\ref{fig:interventions-summary}; Appendices~\\ref{app:extraction}--\\ref{app:entropy}). The pattern reveals a persistent independence-accuracy trade-off. \\emph{Diversity-seeking strategies} (temperature variation, persona sampling) shift $K_\\text{eff}$ by $< 0.5$---insufficient to break correlation. \\emph{Constraint-level interventions} (explicit negation, contrastive prompting) leave the Z3 rejection rate at ${\\sim}3.4\\%$---degeneration persists. \\emph{Debate} ($\\kappa = 0.15$, $\\Delta = -18.6$\\,pp) breaks correlation but collapses accuracy; \\emph{cross-model extraction} leaves $\\kappa$ near the same-model ceiling ($\\kappa \\approx 0.40$--$0.47$). No individual strategy achieves significance after correction (Appendix~\\ref{app:intervention-individual}). Across three model families, self-extraction cannot produce constraints independent of the distributional prior.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig2_interventions_compact.pdf}\n\\caption{Twenty-three of 27 training-free strategies across four categories (four additional strategies tested but omitted for clarity). All produce neutral-to-negative $\\Delta$ vs.\\ SC. Grey band: $\\pm 1$\\,pp noise zone.}\n\\label{fig:interventions-summary}\n\\end{figure}\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic-framework}\n\\label{sec:diagnostics}\n\n\\looseness=-1 Three zero-cost diagnostics predict the outcome of any self-extraction-based aggregation method from a $K = 12$ pilot run: (1) the degenerate-regime indicator $C_0 < 5\\%$ (SICA reduces to SC); (2) the diversity floor $K_\\text{eff} \\leq 1.30$ (insufficient vote diversity for any aggregation gain); (3) the bias ratio BR combined with SC regime (Type~A: SC $\\geq 60\\%$ with BR $> 1$ predicts confirmation-bias degradation; Type~C: SC $\\leq 40\\%$ predicts error amplification). These boundaries correctly characterize the failure mode across all 60 tested conditions (16 main configurations, 27 remediation variants on Mistral-7B${\\times}$FOLIO, and 17 analytical conditions) within the self-extraction paradigm. The framework's practical value lies in failure-mode diagnosis---degenerate, diversity-limited, or confirmation-biased---from a $K{=}12$ pilot run, enabling practitioners to rule out self-extraction before full deployment. Conversely, when diagnostics detect sufficient capability gap (\\S\\ref{sec:cross-arch}), the framework correctly predicts positive gain ($+6.67$\\,pp for Mistral-7B on ProofWriter).\n\n\\looseness=-1 Decision boundaries ($C_0 < 5\\%$, $K_\\text{eff} \\leq 1.30$, SC $< 40\\%$) were derived from Mistral-7B and Qwen2.5-14B. We evaluate prospectively on two held-out generators: LLaMA-3.1-8B (different family) on FOLIO, where the framework predicts Type~A bias and the observed $\\Delta = -4.41$\\,pp confirms; and Qwen3-14B (same family, different generation) on FOLIO and ProofWriter, likewise confirmed ($\\Delta \\leq +1.47$\\,pp, n.s.).",
      "numLines": 133,
      "startLine": 1,
      "totalLines": 133
    }
  },
  "sourceToolAssistantUUID": "11af70ea-2fee-4e50-9de7-1c965907998c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 26 · 2026-05-24T04:28:33.023Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WAST826XrpNuiosMAiUxfs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/diagnosis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "390c5483-622f-499d-8ab7-280d1d848de1",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "b441a2b4-9cec-428f-bc26-f372bb6ef4ba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 27 · 2026-05-24T04:28:33.028Z_

<details><summary>↩ Tool result · `toolu_01WAST826XrpNuiosMAiUxfs`</summary>

```text
1	\section{Diagnosis}
2	\label{sec:diagnosis}
3	
4	Table~\ref{tab:main_results} reports SICA vs.\ SC accuracy across all conditions. None of sixteen non-degenerate conditions shows a significant positive effect ($p < 0.05$); two show significant degradation. We trace this failure to three interconnected mechanisms.
5	
6	\begin{table*}[t]
7	\centering
8	\small
9	\caption{SICA vs.\ SC across all conditions sorted by SC accuracy. $\Delta$ = SICA $-$ SC (pp). $^b$In-context learning with gold logical examples. $\dagger$\,$n < 100$ (suggestive only). \textbf{Bold $\Delta$}: $p < 0.05$ (McNemar). {*}\,$p < 0.05$;\enspace{**}\,$p < 0.01$;\enspace{***}\,$p < 0.001$. Failure modes detailed in Appendix~\ref{app:failure-modes}.}
10	\label{tab:main_results}
11	\begin{tabular}{@{}llrrrrl@{}}
12	\toprule
13	Model & Domain & $n$ & SC (\%) & SICA (\%) & $\Delta$ (pp) & $p$ \\
14	\midrule
15	\multicolumn{7}{l}{\textit{Type C: error amplification (SC $\leq$ 40\%)}} \\
16	Mistral-7B & PW-D5 & 600 & 39.33 & 36.50 & $\mathbf{-2.83}$ & 0.014{*} \\
17	\midrule
18	\multicolumn{7}{l}{\textit{Intermediate SC (SC $\sim$50--60\%, Mistral-7B only)}} \\
19	Mistral-7B & LogiQA & 200 & 50.00 & 51.50 & $+$1.50 & 0.581 \\
20	Mistral-7B & FOLIO (s123) & 204 & 54.41 & 57.35 & $+$2.94 & 0.070 \\
21	Mistral-7B & FOLIO & 204 & 55.88 & 59.31 & $+$3.43 & 0.092 \\
22	Mistral-7B & FOLIO (s456) & 204 & 55.88 & 55.88 & 0.00 & 1.000 \\
23	Mistral-7B & FOLIO (s789) & 204 & 59.31 & 56.86 & $-$2.45 & 0.267 \\
24	\midrule
25	\multicolumn{7}{l}{\textit{Type A: confirmation bias (SC $\geq$ 60\%)}} \\
26	LLaMA-3.1-8B & FOLIO & 204 & 66.18 & 61.76 & $-$4.41 & 0.093 \\
27	LLaMA-3.1-8B & StrategyQA & 200 & 72.00 & 74.00 & $+$2.00 & 0.424 \\
28	Qwen2.5-14B & FOLIO (ICL)$^b$ & 199 & 74.37 & 74.87 & $+$0.50 & 1.000 \\
29	Qwen2.5-14B & PW-D5 & 600 & 74.00 & 71.50 & $\mathbf{-2.50}$ & 0.011{*} \\
30	Qwen2.5-14B & FOLIO & 204 & 75.98 & 75.49 & $-$0.49 & 1.000 \\
31	Qwen2.5-7B & FOLIO & 204 & 75.98 & 76.47 & $+$0.49 & 1.000 \\
32	Qwen2.5-14B & LogiQA & 200 & 79.00 & 78.00 & $-$1.00 & 0.625 \\
33	Qwen3-14B & FOLIO & 204 & 83.33 & 84.80 & $+$1.47 & 1.000 \\
34	Qwen3-14B & PW-D5 & 600 & 85.83 & 85.67 & $-$0.17 & 1.000 \\
35	\midrule
36	\multicolumn{7}{l}{\textit{Degenerate ($C_0 < 5\%$)}} \\
37	QwQ-32B & AIME 2024$^\dagger$ & 22 & 72.70 & 72.70 & 0.00 & \textrm{---} \\
38	Qwen2.5-14B & GSM8K$^\dagger$ & 30 & 96.67 & 96.67 & 0.00 & \textrm{---} \\
39	\midrule
40	\multicolumn{7}{l}{\textit{Oracle upper bound (gold logical annotations + Z3)}} \\
41	Qwen2.5-14B & FOLIO & 204 & 75.98 & \textbf{89.71} & $\mathbf{+13.73}$ & $2.0{\times}10^{-7}${***} \\
42	Qwen2.5-14B & ProofWriter & 600 & 74.00 & \textbf{91.17} & $\mathbf{+17.17}$ & $9.21{\times}10^{-15}${***} \\
43	\bottomrule
44	\end{tabular}
45	\end{table*}
46	
47	\subsection{Symbolic Confirmation Bias}
48	\label{sec:confirmation-bias}
49	\label{sec:effective-k}
50	
51	Table~\ref{tab:independence} reports Fleiss' $\kappa$ and Effective-K (Eq.~\ref{eq:effk}) across 15 conditions at $K = 12$. Among instruction-tuned models, $\kappa$ ranges from 0.21 to 0.82, yielding $K_{\text{eff}} = 1.20\text{--}3.62$. Two conditions are jointly necessary for any positive trend: sufficient $K_{\text{eff}}$ ($\leq 1.30$ never improves) and sufficient SC accuracy ($K_{\text{eff}} = 3.62$ with SC $= 39\%$ produces significant degradation). Cross-model validation confirms universality: all four families produce $\kappa \geq 0.41$ (Table~\ref{tab:kappa_generalization}).
52	
53	This correlation manifests through a specific mechanism: self-extracted constraints systematically confirm the model's majority answer regardless of correctness. On Mistral-7B FOLIO ($n = 204$), when SICA errs, 83.3\% of extracted constraints support the incorrect majority answer---a bias ratio of $4.97\times$ compared to correct problems. Consequently, 94\% of SICA errors overlap with SC errors: symbolic aggregation adds no independent corrective signal.
54	
55	The causal chain is: the model generates an answer, then extracts logical constraints consistent with it. Constraints from majority-answer traces use trace-specific variable names (56.4\% of cross-answer pairs share zero Z3 variables), so MAX-SAT retains nearly all, and aggregation reduces to a weighted majority vote (Eq.~\ref{eq:degenerate}). Confirmation bias generalizes across model families: bias ratios of $4.97\times$ (Mistral-7B), $3.85\times$ (Qwen2.5-14B), and $2.88{\times}^{\dag}$ (LLaMA-3.1-8B) all significantly exceed $1.0$ ($^{\dag}$based on 4/12 traces due to extraction failures; Table~\ref{tab:cross-model-bias}). The oracle ceiling (\S\ref{sec:oracle}) confirms that 75.9\% of the potential gain is lost to self-extraction quality.
56	
57	\begin{table}[t]
58	\centering
59	\small
60	\caption{Trace independence metrics ($K = 12$, sorted by $\kappa$ descending). $\kappa$: Fleiss' Kappa. $K_{\text{eff}}$: Effective-K (Eq.~\ref{eq:effk}). SC: Self-Consistency baseline. $\Delta$: SICA $-$ SC (pp). {*}\,$p < 0.05$; positive $\Delta$ values do not reach significance. multi-T $= T \in \{0.3, 0.7, 1.2\}$, 4 traces each.}
61	\label{tab:independence}
62	\begin{tabular}{@{}llccrr@{}}
63	\toprule
64	Model & Condition & $\kappa$ & $K_{\text{eff}}$ & SC (\%) & $\Delta$ (pp) \\
65	\midrule
66	Qwen3 (think) & FOLIO & 0.91 & 1.09 & ${\sim}$84 & ${\sim}$0 \\
67	Qwen2.5-14B & LogiQA & 0.82 & 1.20 & 79.00 & $-$1.00 \\
68	Qwen3 & FOLIO & 0.77 & 1.26 & 83.33 & $+$1.47 \\
69	Qwen2.5-14B & FOLIO & 0.74 & 1.30 & 75.98 & $-$0.49 \\
70	Qwen2.5-7B & FOLIO & 0.66 & 1.46 & 75.98 & $+$0.49 \\
71	\addlinespace
72	Mistral-7B ($T{=}0.3$) & FOLIO & 0.53 & 1.77 & 58.33 & $-$1.47 \\
73	Mistral-7B & LogiQA & 0.51 & 1.81 & 50.00 & $+$1.50 \\
74	Mistral-7B (s456) & FOLIO & 0.51 & 1.82 & 55.88 & 0.00 \\
75	Mistral-7B & FOLIO & 0.50 & 1.84 & 55.88 & $+$3.43 \\
76	Mistral-7B (s123) & FOLIO & 0.49 & 1.88 & 54.41 & $+$2.94 \\
77	Mistral-7B (s789) & FOLIO & 0.41 & 2.17 & 59.31 & $-$2.45 \\
78	Mistral-7B ($T{=}0.5$) & FOLIO & 0.52 & 1.80 & 58.33 & $-$0.98 \\
79	Mistral-7B (multi-T) & FOLIO & 0.48 & 1.91 & 57.84 & 0.00 \\
80	Mistral-7B ($T{=}1.0$) & FOLIO & 0.48 & 1.91 & 55.39 & 0.00 \\
81	Mistral-7B & PW-D5 & 0.21 & 3.62 & 39.33 & $\mathbf{-2.83}${*} \\
82	\bottomrule
83	\end{tabular}
84	\end{table}
85	
86	
87	\subsection{Process-Level Independence}
88	\label{sec:process-kappa}
89	
90	Answer-level $\kappa$ may underestimate the independence limitation: two traces can follow nearly identical reasoning yet reach different final answers. We define process similarity as the mean pairwise cosine similarity of TF-IDF trace representations:
91	\begin{equation}
92	\label{eq:process-sim}
93	\text{ProcessSim}(q) = \frac{2}{K(K{-}1)} \sum_{i < j} \cos(\mathbf{v}_i^q, \mathbf{v}_j^q),
94	\end{equation}
95	where $\mathbf{v}_i^q$ is the TF-IDF vector of trace $t_i$ for question $q$. On Mistral-7B FOLIO ($n = 204$), mean ProcessSim is $0.69$, far exceeding answer-level $\kappa = 0.41$. These measures are uncorrelated ($r = -0.06$, $p = 0.36$): problems with diverse answers do not exhibit diverse reasoning (Figure~\ref{fig:process-kappa}). This gap implies that interventions targeting answer diversity (temperature scaling, diverse prompting) may spread answers without altering reasoning paths.
96	
97	\begin{figure}[t]
98	\centering
99	\includegraphics[width=0.85\columnwidth]{figures/fig3_process_kappa_scatter.pdf}
100	\vspace{-2mm}
101	\caption{Answer agreement vs.\ CoT cosine similarity (Mistral-7B, FOLIO, $n{=}204$). Flat regression ($r = -0.06$, $p = 0.36$): process and answer independence are uncorrelated.}
102	\label{fig:process-kappa}
103	\end{figure}
104	
105	
106	\subsection{Regime-Dependent Effects}
107	\label{sec:main-results}
108	\label{sec:diagnostics}
109	
110	SICA effectiveness depends sharply on the accuracy regime (Figure~\ref{fig:regime-scatter}).
111	
112	\paragraph{Intermediate-SC region.} Mistral-7B on FOLIO (SC $\sim$50--60\%) shows positive directional trends in 2 of 4 seeds: $\Delta = +3.43$\,pp ($p = 0.092$) and $+2.94$\,pp ($p = 0.070$); the remaining seeds show null or negative results. No seed reaches $p < 0.05$; the 4-seed mean is $+1.47$\,pp. The default-seed and seed-456 runs share identical SC baselines (55.88\%) yet diverge ($+3.43$ vs.\ $0.00$\,pp), suggesting that seed-level constraint quality, not SC level alone, influences the effect.
113	
114	\paragraph{Type A (SC $\geq$ 60\%).} All nine Type~A conditions produce no significant positive effects. Even in-context learning with gold logical examples yields $\Delta = +0.50$\,pp (n.s.). Qwen2.5-14B on ProofWriter shows significant degradation ($\Delta = -2.50$\,pp, $p = 0.011$).
115	
116	\paragraph{Type C (SC $\leq$ 40\%).} Mistral-7B on ProofWriter ($n = 600$, SC $= 39.33\%$) shows $\Delta = -2.83$\,pp ($p = 0.014$): SICA \emph{significantly hurts} by formalizing incorrect reasoning. When $C_0 < 5\%$, nearly all traces agree and SICA reduces to SC by construction.
117	
118	Four supporting analyses confirm the mechanism: constraint ablation shows both MAX-SAT and count-only each agree with SC on ${>}$96\% of predictions ($n = 804$; Table~\ref{tab:ablation}); 91.8\% of constraints are discriminative but mirror the majority; effects concentrate in high-entropy problems ($+12.8$\,pp) with direction determined by accuracy regime; and hyperparameter peaks coincide with low SC baselines (Appendices~\ref{app:extraction}--\ref{app:entropy}).
119	
120	\begin{figure}[t]
121	\centering
122	\includegraphics[width=\columnwidth]{f2_regime_scatter}
123	\caption{SICA $\Delta$ (pp) vs.\ SC baseline. Filled: $n \geq 100$; open: $n < 100$. The intermediate-SC region (50--60\%, shaded) contains the only positive trends (none reaching $p < 0.05$). Type~C: significant degradation ($p = 0.014$).}
124	\label{fig:regime-scatter}
125	\end{figure}
126	
127	
128	\subsection{Remediation: 25+ Strategies Fail}
129	\label{sec:remediation}
130	\label{sec:interventions}
131	
132	We test more than twenty remediation strategies spanning prompt engineering, method-level redesign, and ten additional directions. All produce neutral or negative results.
133	
134	\paragraph{Prompt-level interventions.} Nine strategies spanning six dimensions (Appendix Table~\ref{tab:remediation}) all fail. Contrastive prompting reduces non-discriminative constraints from 8.2\% to 6.0\%, but newly discriminative constraints still mirror the majority ($\Delta = -1.1$\,pp). Cross-model extraction fails in both directions: weaker models yield 0\% discriminative constraints; stronger models produce accuracy within $\pm 1$\,pp of self-extraction. Multi-temperature sampling ($T \in \{0.3, 0.7, 1.2\}$) yields $\Delta = 0.00$\,pp.
135	
136	\paragraph{Method-level interventions.} ICG ($\Delta \approx 0$, $p = .206$), Contrastive ($\Delta = -9.31$\,pp, $p < 0.01$), and Debate ($\Delta = -18.63$/$-23.00$\,pp, $p < 0.001$) all fail (Table~\ref{tab:method_interventions}, Appendix~\ref{app:remediation}). Ten further experiments (code verification, iterative refinement, logprob filtering, cross-model ensembles) produce neutral-to-negative results (Appendix Table~\ref{tab:additional_interventions}).
137	
138	\paragraph{Independence-accuracy trade-off.} Table~\ref{tab:kappa_generalization} compares Fleiss' $\kappa$ across four aggregation methods and three model families (Figure~\ref{fig:kappa-accuracy}). SC ($\kappa = 0.44$), Diverse-Prompt ($\kappa = 0.40$), and ICG ($\kappa = 0.47$) cluster at $\kappa \approx 0.40$--$0.47$; Debate reaches $\kappa = 0.15$ but collapses accuracy by $-18.6$\,pp. All three families cluster above $\kappa = 0.40$, forming a same-model trade-off ceiling: methods that increase independence destroy accuracy, and methods preserving accuracy cannot break the correlation floor. The bias ratio gradient ($4.97\times$ Mistral $> 3.85\times$ Qwen $> 2.88\times$ LLaMA) suggests weaker models suffer more severe confirmation bias; all models exceed $1.0$, a pattern that persists from 7B open-source to frontier closed-source (BR $1.66$--$4.97\times$; Table~\ref{tab:frontier-scb}). For practitioners, $C_0$ combined with SC accuracy predicts when augmentation is unlikely to help: $C_0 < 5\%$ implies degeneration, SC $\geq 60\%$ implies confirmation bias, SC $\leq 40\%$ implies error amplification. Whether trained extractors shift the observed trade-off boundary remains open.
139	
140	\begin{table}[t]
141	\centering
142	\small
143	\caption{Independence-accuracy trade-off (FOLIO, $n = 204$). Top: aggregation methods on Mistral-7B; bottom: SC across three model families. All families produce $\kappa \geq 0.41$, confirming an architecture-independent ceiling. $\kappa$: Fleiss' kappa on raw answers.}
144	\label{tab:kappa_generalization}
145	\setlength{\tabcolsep}{3.5pt}
146	\begin{tabular}{@{}llccrr@{}}
147	\toprule
148	Model & Aggregation & $\kappa$ & Eff-$K$ & $K$ & Acc.\ (\%) \\
149	\midrule
150	Mistral-7B & Debate & 0.15 & 4.44 & 12 & 38.24 \\
151	& Diverse-Prompt & 0.40 & 2.21 & 12 & 54.41 \\
152	& Self-Consistency & 0.44 & 2.02 & 10 & 56.86 \\
153	& ICG & 0.47 & 1.93 & 10 & 51.96 \\
154	\addlinespace
155	LLaMA-3.1-8B & Self-Consistency & 0.41 & 2.17 & 12 & 66.18 \\
156	Qwen2.5-7B & Self-Consistency & 0.66 & 1.46 & 12 & 75.98 \\
157	Qwen2.5-14B & Self-Consistency & 0.74 & 1.32 & 12 & 75.98 \\
158	\bottomrule
159	\end{tabular}
160	\end{table}
161	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b441a2b4-9cec-428f-bc26-f372bb6ef4ba",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "fea0be37-08b9-4a68-847b-0366c4e7f194",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/diagnosis.tex",
      "content": "\\section{Diagnosis}\n\\label{sec:diagnosis}\n\nTable~\\ref{tab:main_results} reports SICA vs.\\ SC accuracy across all conditions. None of sixteen non-degenerate conditions shows a significant positive effect ($p < 0.05$); two show significant degradation. We trace this failure to three interconnected mechanisms.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{SICA vs.\\ SC across all conditions sorted by SC accuracy. $\\Delta$ = SICA $-$ SC (pp). $^b$In-context learning with gold logical examples. $\\dagger$\\,$n < 100$ (suggestive only). \\textbf{Bold $\\Delta$}: $p < 0.05$ (McNemar). {*}\\,$p < 0.05$;\\enspace{**}\\,$p < 0.01$;\\enspace{***}\\,$p < 0.001$. Failure modes detailed in Appendix~\\ref{app:failure-modes}.}\n\\label{tab:main_results}\n\\begin{tabular}{@{}llrrrrl@{}}\n\\toprule\nModel & Domain & $n$ & SC (\\%) & SICA (\\%) & $\\Delta$ (pp) & $p$ \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Type C: error amplification (SC $\\leq$ 40\\%)}} \\\\\nMistral-7B & PW-D5 & 600 & 39.33 & 36.50 & $\\mathbf{-2.83}$ & 0.014{*} \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Intermediate SC (SC $\\sim$50--60\\%, Mistral-7B only)}} \\\\\nMistral-7B & LogiQA & 200 & 50.00 & 51.50 & $+$1.50 & 0.581 \\\\\nMistral-7B & FOLIO (s123) & 204 & 54.41 & 57.35 & $+$2.94 & 0.070 \\\\\nMistral-7B & FOLIO & 204 & 55.88 & 59.31 & $+$3.43 & 0.092 \\\\\nMistral-7B & FOLIO (s456) & 204 & 55.88 & 55.88 & 0.00 & 1.000 \\\\\nMistral-7B & FOLIO (s789) & 204 & 59.31 & 56.86 & $-$2.45 & 0.267 \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Type A: confirmation bias (SC $\\geq$ 60\\%)}} \\\\\nLLaMA-3.1-8B & FOLIO & 204 & 66.18 & 61.76 & $-$4.41 & 0.093 \\\\\nLLaMA-3.1-8B & StrategyQA & 200 & 72.00 & 74.00 & $+$2.00 & 0.424 \\\\\nQwen2.5-14B & FOLIO (ICL)$^b$ & 199 & 74.37 & 74.87 & $+$0.50 & 1.000 \\\\\nQwen2.5-14B & PW-D5 & 600 & 74.00 & 71.50 & $\\mathbf{-2.50}$ & 0.011{*} \\\\\nQwen2.5-14B & FOLIO & 204 & 75.98 & 75.49 & $-$0.49 & 1.000 \\\\\nQwen2.5-7B & FOLIO & 204 & 75.98 & 76.47 & $+$0.49 & 1.000 \\\\\nQwen2.5-14B & LogiQA & 200 & 79.00 & 78.00 & $-$1.00 & 0.625 \\\\\nQwen3-14B & FOLIO & 204 & 83.33 & 84.80 & $+$1.47 & 1.000 \\\\\nQwen3-14B & PW-D5 & 600 & 85.83 & 85.67 & $-$0.17 & 1.000 \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Degenerate ($C_0 < 5\\%$)}} \\\\\nQwQ-32B & AIME 2024$^\\dagger$ & 22 & 72.70 & 72.70 & 0.00 & \\textrm{---} \\\\\nQwen2.5-14B & GSM8K$^\\dagger$ & 30 & 96.67 & 96.67 & 0.00 & \\textrm{---} \\\\\n\\midrule\n\\multicolumn{7}{l}{\\textit{Oracle upper bound (gold logical annotations + Z3)}} \\\\\nQwen2.5-14B & FOLIO & 204 & 75.98 & \\textbf{89.71} & $\\mathbf{+13.73}$ & $2.0{\\times}10^{-7}${***} \\\\\nQwen2.5-14B & ProofWriter & 600 & 74.00 & \\textbf{91.17} & $\\mathbf{+17.17}$ & $9.21{\\times}10^{-15}${***} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Symbolic Confirmation Bias}\n\\label{sec:confirmation-bias}\n\\label{sec:effective-k}\n\nTable~\\ref{tab:independence} reports Fleiss' $\\kappa$ and Effective-K (Eq.~\\ref{eq:effk}) across 15 conditions at $K = 12$. Among instruction-tuned models, $\\kappa$ ranges from 0.21 to 0.82, yielding $K_{\\text{eff}} = 1.20\\text{--}3.62$. Two conditions are jointly necessary for any positive trend: sufficient $K_{\\text{eff}}$ ($\\leq 1.30$ never improves) and sufficient SC accuracy ($K_{\\text{eff}} = 3.62$ with SC $= 39\\%$ produces significant degradation). Cross-model validation confirms universality: all four families produce $\\kappa \\geq 0.41$ (Table~\\ref{tab:kappa_generalization}).\n\nThis correlation manifests through a specific mechanism: self-extracted constraints systematically confirm the model's majority answer regardless of correctness. On Mistral-7B FOLIO ($n = 204$), when SICA errs, 83.3\\% of extracted constraints support the incorrect majority answer---a bias ratio of $4.97\\times$ compared to correct problems. Consequently, 94\\% of SICA errors overlap with SC errors: symbolic aggregation adds no independent corrective signal.\n\nThe causal chain is: the model generates an answer, then extracts logical constraints consistent with it. Constraints from majority-answer traces use trace-specific variable names (56.4\\% of cross-answer pairs share zero Z3 variables), so MAX-SAT retains nearly all, and aggregation reduces to a weighted majority vote (Eq.~\\ref{eq:degenerate}). Confirmation bias generalizes across model families: bias ratios of $4.97\\times$ (Mistral-7B), $3.85\\times$ (Qwen2.5-14B), and $2.88{\\times}^{\\dag}$ (LLaMA-3.1-8B) all significantly exceed $1.0$ ($^{\\dag}$based on 4/12 traces due to extraction failures; Table~\\ref{tab:cross-model-bias}). The oracle ceiling (\\S\\ref{sec:oracle}) confirms that 75.9\\% of the potential gain is lost to self-extraction quality.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Trace independence metrics ($K = 12$, sorted by $\\kappa$ descending). $\\kappa$: Fleiss' Kappa. $K_{\\text{eff}}$: Effective-K (Eq.~\\ref{eq:effk}). SC: Self-Consistency baseline. $\\Delta$: SICA $-$ SC (pp). {*}\\,$p < 0.05$; positive $\\Delta$ values do not reach significance. multi-T $= T \\in \\{0.3, 0.7, 1.2\\}$, 4 traces each.}\n\\label{tab:independence}\n\\begin{tabular}{@{}llccrr@{}}\n\\toprule\nModel & Condition & $\\kappa$ & $K_{\\text{eff}}$ & SC (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\nQwen3 (think) & FOLIO & 0.91 & 1.09 & ${\\sim}$84 & ${\\sim}$0 \\\\\nQwen2.5-14B & LogiQA & 0.82 & 1.20 & 79.00 & $-$1.00 \\\\\nQwen3 & FOLIO & 0.77 & 1.26 & 83.33 & $+$1.47 \\\\\nQwen2.5-14B & FOLIO & 0.74 & 1.30 & 75.98 & $-$0.49 \\\\\nQwen2.5-7B & FOLIO & 0.66 & 1.46 & 75.98 & $+$0.49 \\\\\n\\addlinespace\nMistral-7B ($T{=}0.3$) & FOLIO & 0.53 & 1.77 & 58.33 & $-$1.47 \\\\\nMistral-7B & LogiQA & 0.51 & 1.81 & 50.00 & $+$1.50 \\\\\nMistral-7B (s456) & FOLIO & 0.51 & 1.82 & 55.88 & 0.00 \\\\\nMistral-7B & FOLIO & 0.50 & 1.84 & 55.88 & $+$3.43 \\\\\nMistral-7B (s123) & FOLIO & 0.49 & 1.88 & 54.41 & $+$2.94 \\\\\nMistral-7B (s789) & FOLIO & 0.41 & 2.17 & 59.31 & $-$2.45 \\\\\nMistral-7B ($T{=}0.5$) & FOLIO & 0.52 & 1.80 & 58.33 & $-$0.98 \\\\\nMistral-7B (multi-T) & FOLIO & 0.48 & 1.91 & 57.84 & 0.00 \\\\\nMistral-7B ($T{=}1.0$) & FOLIO & 0.48 & 1.91 & 55.39 & 0.00 \\\\\nMistral-7B & PW-D5 & 0.21 & 3.62 & 39.33 & $\\mathbf{-2.83}${*} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Process-Level Independence}\n\\label{sec:process-kappa}\n\nAnswer-level $\\kappa$ may underestimate the independence limitation: two traces can follow nearly identical reasoning yet reach different final answers. We define process similarity as the mean pairwise cosine similarity of TF-IDF trace representations:\n\\begin{equation}\n\\label{eq:process-sim}\n\\text{ProcessSim}(q) = \\frac{2}{K(K{-}1)} \\sum_{i < j} \\cos(\\mathbf{v}_i^q, \\mathbf{v}_j^q),\n\\end{equation}\nwhere $\\mathbf{v}_i^q$ is the TF-IDF vector of trace $t_i$ for question $q$. On Mistral-7B FOLIO ($n = 204$), mean ProcessSim is $0.69$, far exceeding answer-level $\\kappa = 0.41$. These measures are uncorrelated ($r = -0.06$, $p = 0.36$): problems with diverse answers do not exhibit diverse reasoning (Figure~\\ref{fig:process-kappa}). This gap implies that interventions targeting answer diversity (temperature scaling, diverse prompting) may spread answers without altering reasoning paths.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig3_process_kappa_scatter.pdf}\n\\vspace{-2mm}\n\\caption{Answer agreement vs.\\ CoT cosine similarity (Mistral-7B, FOLIO, $n{=}204$). Flat regression ($r = -0.06$, $p = 0.36$): process and answer independence are uncorrelated.}\n\\label{fig:process-kappa}\n\\end{figure}\n\n\n\\subsection{Regime-Dependent Effects}\n\\label{sec:main-results}\n\\label{sec:diagnostics}\n\nSICA effectiveness depends sharply on the accuracy regime (Figure~\\ref{fig:regime-scatter}).\n\n\\paragraph{Intermediate-SC region.} Mistral-7B on FOLIO (SC $\\sim$50--60\\%) shows positive directional trends in 2 of 4 seeds: $\\Delta = +3.43$\\,pp ($p = 0.092$) and $+2.94$\\,pp ($p = 0.070$); the remaining seeds show null or negative results. No seed reaches $p < 0.05$; the 4-seed mean is $+1.47$\\,pp. The default-seed and seed-456 runs share identical SC baselines (55.88\\%) yet diverge ($+3.43$ vs.\\ $0.00$\\,pp), suggesting that seed-level constraint quality, not SC level alone, influences the effect.\n\n\\paragraph{Type A (SC $\\geq$ 60\\%).} All nine Type~A conditions produce no significant positive effects. Even in-context learning with gold logical examples yields $\\Delta = +0.50$\\,pp (n.s.). Qwen2.5-14B on ProofWriter shows significant degradation ($\\Delta = -2.50$\\,pp, $p = 0.011$).\n\n\\paragraph{Type C (SC $\\leq$ 40\\%).} Mistral-7B on ProofWriter ($n = 600$, SC $= 39.33\\%$) shows $\\Delta = -2.83$\\,pp ($p = 0.014$): SICA \\emph{significantly hurts} by formalizing incorrect reasoning. When $C_0 < 5\\%$, nearly all traces agree and SICA reduces to SC by construction.\n\nFour supporting analyses confirm the mechanism: constraint ablation shows both MAX-SAT and count-only each agree with SC on ${>}$96\\% of predictions ($n = 804$; Table~\\ref{tab:ablation}); 91.8\\% of constraints are discriminative but mirror the majority; effects concentrate in high-entropy problems ($+12.8$\\,pp) with direction determined by accuracy regime; and hyperparameter peaks coincide with low SC baselines (Appendices~\\ref{app:extraction}--\\ref{app:entropy}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{f2_regime_scatter}\n\\caption{SICA $\\Delta$ (pp) vs.\\ SC baseline. Filled: $n \\geq 100$; open: $n < 100$. The intermediate-SC region (50--60\\%, shaded) contains the only positive trends (none reaching $p < 0.05$). Type~C: significant degradation ($p = 0.014$).}\n\\label{fig:regime-scatter}\n\\end{figure}\n\n\n\\subsection{Remediation: 25+ Strategies Fail}\n\\label{sec:remediation}\n\\label{sec:interventions}\n\nWe test more than twenty remediation strategies spanning prompt engineering, method-level redesign, and ten additional directions. All produce neutral or negative results.\n\n\\paragraph{Prompt-level interventions.} Nine strategies spanning six dimensions (Appendix Table~\\ref{tab:remediation}) all fail. Contrastive prompting reduces non-discriminative constraints from 8.2\\% to 6.0\\%, but newly discriminative constraints still mirror the majority ($\\Delta = -1.1$\\,pp). Cross-model extraction fails in both directions: weaker models yield 0\\% discriminative constraints; stronger models produce accuracy within $\\pm 1$\\,pp of self-extraction. Multi-temperature sampling ($T \\in \\{0.3, 0.7, 1.2\\}$) yields $\\Delta = 0.00$\\,pp.\n\n\\paragraph{Method-level interventions.} ICG ($\\Delta \\approx 0$, $p = .206$), Contrastive ($\\Delta = -9.31$\\,pp, $p < 0.01$), and Debate ($\\Delta = -18.63$/$-23.00$\\,pp, $p < 0.001$) all fail (Table~\\ref{tab:method_interventions}, Appendix~\\ref{app:remediation}). Ten further experiments (code verification, iterative refinement, logprob filtering, cross-model ensembles) produce neutral-to-negative results (Appendix Table~\\ref{tab:additional_interventions}).\n\n\\paragraph{Independence-accuracy trade-off.} Table~\\ref{tab:kappa_generalization} compares Fleiss' $\\kappa$ across four aggregation methods and three model families (Figure~\\ref{fig:kappa-accuracy}). SC ($\\kappa = 0.44$), Diverse-Prompt ($\\kappa = 0.40$), and ICG ($\\kappa = 0.47$) cluster at $\\kappa \\approx 0.40$--$0.47$; Debate reaches $\\kappa = 0.15$ but collapses accuracy by $-18.6$\\,pp. All three families cluster above $\\kappa = 0.40$, forming a same-model trade-off ceiling: methods that increase independence destroy accuracy, and methods preserving accuracy cannot break the correlation floor. The bias ratio gradient ($4.97\\times$ Mistral $> 3.85\\times$ Qwen $> 2.88\\times$ LLaMA) suggests weaker models suffer more severe confirmation bias; all models exceed $1.0$, a pattern that persists from 7B open-source to frontier closed-source (BR $1.66$--$4.97\\times$; Table~\\ref{tab:frontier-scb}). For practitioners, $C_0$ combined with SC accuracy predicts when augmentation is unlikely to help: $C_0 < 5\\%$ implies degeneration, SC $\\geq 60\\%$ implies confirmation bias, SC $\\leq 40\\%$ implies error amplification. Whether trained extractors shift the observed trade-off boundary remains open.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Independence-accuracy trade-off (FOLIO, $n = 204$). Top: aggregation methods on Mistral-7B; bottom: SC across three model families. All families produce $\\kappa \\geq 0.41$, confirming an architecture-independent ceiling. $\\kappa$: Fleiss' kappa on raw answers.}\n\\label{tab:kappa_generalization}\n\\setlength{\\tabcolsep}{3.5pt}\n\\begin{tabular}{@{}llccrr@{}}\n\\toprule\nModel & Aggregation & $\\kappa$ & Eff-$K$ & $K$ & Acc.\\ (\\%) \\\\\n\\midrule\nMistral-7B & Debate & 0.15 & 4.44 & 12 & 38.24 \\\\\n& Diverse-Prompt & 0.40 & 2.21 & 12 & 54.41 \\\\\n& Self-Consistency & 0.44 & 2.02 & 10 & 56.86 \\\\\n& ICG & 0.47 & 1.93 & 10 & 51.96 \\\\\n\\addlinespace\nLLaMA-3.1-8B & Self-Consistency & 0.41 & 2.17 & 12 & 66.18 \\\\\nQwen2.5-7B & Self-Consistency & 0.66 & 1.46 & 12 & 75.98 \\\\\nQwen2.5-14B & Self-Consistency & 0.74 & 1.32 & 12 & 75.98 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n",
      "numLines": 161,
      "startLine": 1,
      "totalLines": 161
    }
  },
  "sourceToolAssistantUUID": "b441a2b4-9cec-428f-bc26-f372bb6ef4ba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 28 · 2026-05-24T04:28:33.506Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Xi7UFYhM5PAFhcqXLVMQWi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/solutions.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fea0be37-08b9-4a68-847b-0366c4e7f194",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "6d831866-9170-4c75-bbbe-0bd0271d8004",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 29 · 2026-05-24T04:28:33.510Z_

<details><summary>↩ Tool result · `toolu_01Xi7UFYhM5PAFhcqXLVMQWi`</summary>

```text
1	\section{Escaping the Bottleneck}
2	\label{sec:solutions}
3	\label{sec:cross-arch}
4	
5	\paragraph{Motivation.}
6	\looseness=-1 No training-free self-extraction method achieves independence from the model's distributional prior (\S\ref{sec:remediation}). The DPI bound implies that any escape must break the self-extraction dependency: $I(C;Y) \leq I(T;Y)$ binds whenever constraints are deterministic functions of the generating model's traces. We test whether a structurally independent verifier, sharing neither architecture nor training data with the generator, provides corrective signal that escapes this bound.
7	
8	\paragraph{Method.}
9	\looseness=-1 We use DeBERTa-large \citep{he2021deberta} (406M, encoder-only), fine-tuned on MultiNLI \citep{williams2018mnli}, to classify (premise, conclusion) pairs as entailment, contradiction, or neutral. In combo mode, each NLI-supporting vote counts $w$ times alongside SC's $K$ votes. We evaluate on Mistral-7B FOLIO ($n = 204$) and ProofWriter depth-5 ($n = 600$).
10	
11	\paragraph{Zero-shot results.}
12	\looseness=-1 DeBERTa NLI alone achieves 49.51\% on FOLIO and 55.00\% on ProofWriter. Combo $w{=}3$ yields $+6.67$\,pp on ProofWriter for Mistral-7B ($p < 0.001$, significant after BH correction) and $+2.94$\,pp on FOLIO (n.s.); all generators with SC $\geq 72\%$ show no significant improvement ($\Delta \leq +1.47$\,pp). Same-model SICA \emph{degrades} ProofWriter ($-2.83$\,pp; Table~\ref{tab:main_results}), illustrating that corrective signal must originate outside the model's distribution.
13	
14	\paragraph{Capability gap.}
15	\looseness=-1 Across 108 verifier-generator-weight combinations spanning three NLI architectures, four generators, and three domains, gain decreases monotonically with generator accuracy---a \emph{capability-gap pattern}. Of 72 above-verifier conditions, none shows a significant improvement; all significant gains concentrate below the verifier's standalone accuracy. The pattern is quantified by a perfect rank correlation across architectures ($\rho = 1.0$, $p = 0.003$, $n{=}6$; Figure~\ref{fig:capability-gap}). On ProofWriter ($n{=}600$; Table~\ref{tab:cross_generator_nli}), only Mistral-7B (SC below DeBERTa's 55.00\%) gains significantly ($+6.67$\,pp, $p < 0.001$). At $w{=}5$, BART and RoBERTa \emph{degrade} Qwen2.5-14B ($-3.43$/$-4.41$\,pp; Appendix~\ref{app:multi-nli}).
16	
17	\begin{table}[t]
18	\centering
19	\small
20	\caption{Cross-generator NLI escape with DeBERTa-large-mnli verifier (55.00\% standalone, ProofWriter $n{=}600$). Combo gain decreases monotonically with generator capability. Only Mistral-7B (SC below the verifier) shows a significant $w{=}3$ gain.}
21	\label{tab:cross_generator_nli}
22	\resizebox{\columnwidth}{!}{\begin{tabular}{@{}llcccc@{}}
23	\toprule
24	Generator & Family & SC & Gap & Combo $\Delta$ ($w{=}3$) & $p$ \\
25	\midrule
26	Mistral-7B & Mistral & 39.33\% & $+$15.67 & $+$6.67\,pp & $<$0.001 \\
27	LLaMA-3.1-8B & LLaMA & 72.50\% & $-$17.50 & $+$0.83\,pp & 0.665 \\
28	Qwen2.5-14B & Qwen & 74.00\% & $-$19.00 & $+$0.67\,pp & 0.503 \\
29	Qwen3-14B & Qwen & 85.83\% & $-$30.83 & $+$0.50\,pp & 0.453 \\
30	\bottomrule
31	\end{tabular}}
32	\end{table}
33	
34	\paragraph{Domain-adapted verifier.}
35	\looseness=-1 Fine-tuning DeBERTa on ProofWriter depth-5 OWA (99.67\% standalone) amplifies escape: $+$12.67/$+$11.67\,pp for Mistral-7B/LLaMA-8B ($14\times$ over zero-shot; Table~\ref{tab:finetuned-nli}), extending gains to generators with SC up to ${\sim}$72\%. A cost-aware cascade recovers 83--90\% of gain at ${\sim}$35\% cost (Appendix~\ref{app:drc}). These results serve as directional evidence (the domain-adapted verifier introduces training).
36	
37	\paragraph{Cross-model voting vs.\ cross-architecture NLI.}
38	\looseness=-1 An ensemble diversity control replaces the NLI verifier with a second LLM as cross voter ($w{=}3$). With Mistral-7B as cross voter on ProofWriter, all three strong generators degrade significantly ($-2.33$ to $-9.33$\,pp, all $p \leq 0.020$); even a stronger cross voter (Qwen2.5-14B) degrades Qwen3-14B at $w{=}5$ ($-2.50$\,pp, $p = 0.006$). In contrast, DeBERTa NLI at comparable standalone accuracy (55.00\%) never degrades any generator ($\Delta \leq +0.83$\,pp). This asymmetry reflects the structural independence of encoder-only NLI---different architecture, training objective, and input representation---from autoregressive biases shared across LLM families (Table~\ref{tab:cross-model-ablation}).
39	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6d831866-9170-4c75-bbbe-0bd0271d8004",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "cb323981-8505-4458-a9dc-ef8a15690e73",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/solutions.tex",
      "content": "\\section{Escaping the Bottleneck}\n\\label{sec:solutions}\n\\label{sec:cross-arch}\n\n\\paragraph{Motivation.}\n\\looseness=-1 No training-free self-extraction method achieves independence from the model's distributional prior (\\S\\ref{sec:remediation}). The DPI bound implies that any escape must break the self-extraction dependency: $I(C;Y) \\leq I(T;Y)$ binds whenever constraints are deterministic functions of the generating model's traces. We test whether a structurally independent verifier, sharing neither architecture nor training data with the generator, provides corrective signal that escapes this bound.\n\n\\paragraph{Method.}\n\\looseness=-1 We use DeBERTa-large \\citep{he2021deberta} (406M, encoder-only), fine-tuned on MultiNLI \\citep{williams2018mnli}, to classify (premise, conclusion) pairs as entailment, contradiction, or neutral. In combo mode, each NLI-supporting vote counts $w$ times alongside SC's $K$ votes. We evaluate on Mistral-7B FOLIO ($n = 204$) and ProofWriter depth-5 ($n = 600$).\n\n\\paragraph{Zero-shot results.}\n\\looseness=-1 DeBERTa NLI alone achieves 49.51\\% on FOLIO and 55.00\\% on ProofWriter. Combo $w{=}3$ yields $+6.67$\\,pp on ProofWriter for Mistral-7B ($p < 0.001$, significant after BH correction) and $+2.94$\\,pp on FOLIO (n.s.); all generators with SC $\\geq 72\\%$ show no significant improvement ($\\Delta \\leq +1.47$\\,pp). Same-model SICA \\emph{degrades} ProofWriter ($-2.83$\\,pp; Table~\\ref{tab:main_results}), illustrating that corrective signal must originate outside the model's distribution.\n\n\\paragraph{Capability gap.}\n\\looseness=-1 Across 108 verifier-generator-weight combinations spanning three NLI architectures, four generators, and three domains, gain decreases monotonically with generator accuracy---a \\emph{capability-gap pattern}. Of 72 above-verifier conditions, none shows a significant improvement; all significant gains concentrate below the verifier's standalone accuracy. The pattern is quantified by a perfect rank correlation across architectures ($\\rho = 1.0$, $p = 0.003$, $n{=}6$; Figure~\\ref{fig:capability-gap}). On ProofWriter ($n{=}600$; Table~\\ref{tab:cross_generator_nli}), only Mistral-7B (SC below DeBERTa's 55.00\\%) gains significantly ($+6.67$\\,pp, $p < 0.001$). At $w{=}5$, BART and RoBERTa \\emph{degrade} Qwen2.5-14B ($-3.43$/$-4.41$\\,pp; Appendix~\\ref{app:multi-nli}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-generator NLI escape with DeBERTa-large-mnli verifier (55.00\\% standalone, ProofWriter $n{=}600$). Combo gain decreases monotonically with generator capability. Only Mistral-7B (SC below the verifier) shows a significant $w{=}3$ gain.}\n\\label{tab:cross_generator_nli}\n\\resizebox{\\columnwidth}{!}{\\begin{tabular}{@{}llcccc@{}}\n\\toprule\nGenerator & Family & SC & Gap & Combo $\\Delta$ ($w{=}3$) & $p$ \\\\\n\\midrule\nMistral-7B & Mistral & 39.33\\% & $+$15.67 & $+$6.67\\,pp & $<$0.001 \\\\\nLLaMA-3.1-8B & LLaMA & 72.50\\% & $-$17.50 & $+$0.83\\,pp & 0.665 \\\\\nQwen2.5-14B & Qwen & 74.00\\% & $-$19.00 & $+$0.67\\,pp & 0.503 \\\\\nQwen3-14B & Qwen & 85.83\\% & $-$30.83 & $+$0.50\\,pp & 0.453 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Domain-adapted verifier.}\n\\looseness=-1 Fine-tuning DeBERTa on ProofWriter depth-5 OWA (99.67\\% standalone) amplifies escape: $+$12.67/$+$11.67\\,pp for Mistral-7B/LLaMA-8B ($14\\times$ over zero-shot; Table~\\ref{tab:finetuned-nli}), extending gains to generators with SC up to ${\\sim}$72\\%. A cost-aware cascade recovers 83--90\\% of gain at ${\\sim}$35\\% cost (Appendix~\\ref{app:drc}). These results serve as directional evidence (the domain-adapted verifier introduces training).\n\n\\paragraph{Cross-model voting vs.\\ cross-architecture NLI.}\n\\looseness=-1 An ensemble diversity control replaces the NLI verifier with a second LLM as cross voter ($w{=}3$). With Mistral-7B as cross voter on ProofWriter, all three strong generators degrade significantly ($-2.33$ to $-9.33$\\,pp, all $p \\leq 0.020$); even a stronger cross voter (Qwen2.5-14B) degrades Qwen3-14B at $w{=}5$ ($-2.50$\\,pp, $p = 0.006$). In contrast, DeBERTa NLI at comparable standalone accuracy (55.00\\%) never degrades any generator ($\\Delta \\leq +0.83$\\,pp). This asymmetry reflects the structural independence of encoder-only NLI---different architecture, training objective, and input representation---from autoregressive biases shared across LLM families (Table~\\ref{tab:cross-model-ablation}).\n",
      "numLines": 39,
      "startLine": 1,
      "totalLines": 39
    }
  },
  "sourceToolAssistantUUID": "6d831866-9170-4c75-bbbe-0bd0271d8004",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 30 · 2026-05-24T04:28:34.003Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GYTRX29rhB7KGu2hNfoxCi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cb323981-8505-4458-a9dc-ef8a15690e73",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "2ddea886-a82d-4c02-b11c-40177412f781",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 31 · 2026-05-24T04:28:34.009Z_

<details><summary>↩ Tool result · `toolu_01GYTRX29rhB7KGu2hNfoxCi`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	\label{sec:conclusion}
4	
5	\looseness=-1
6	Our central finding is that the value of formal verification depends on the \emph{independence} of its inputs, not the soundness of its logic. \emph{SICA-specific}: under source-attribution scoring, SICA reduces to majority vote (Observation~1), and 27 training-free variants fail to escape. \emph{General}: the DPI bound applies to any deterministic self-extraction, and symbolic confirmation bias---a persistent empirical pattern across all tested zero-shot self-extraction conditions, not a cognitive bias analogy---holds across nine models (7B to frontier), suggesting the bottleneck is intrinsic to self-referential constraint generation. Three diagnostics ($K_\text{eff}$, BR, $C_0$) correctly characterize failure modes across all tested conditions, with boundaries generalizing to held-out families (\S\ref{sec:diagnostic-framework}).
7	
8	\looseness=-1
9	These results connect to ensemble diversity theory \citep{dietterich2000ensemble, krogh1994neural}: with $K_\text{eff} \leq 3.62$ for $K{=}12$, same-model traces scale redundancy, not information. For test-time compute scaling \citep{snell2025scaling}, increasing $K$ within a single model yields diminishing returns when traces share systematic biases.
10	
11	\looseness=-1
12	Escaping the bottleneck requires structural independence (\S\ref{sec:cross-arch}); cross-architecture NLI provides a proof of concept, but whether trained extractors or hybrid approaches can shift the boundary remains open. Our diagnostic framework offers a concrete tool: a $K{=}12$ pilot run with three zero-cost metrics predicts whether any self-extraction method will help before full deployment.
13	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2ddea886-a82d-4c02-b11c-40177412f781",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "afdf4375-71de-49c5-9ff4-5ec5f464d954",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/discussion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\\label{sec:conclusion}\n\n\\looseness=-1\nOur central finding is that the value of formal verification depends on the \\emph{independence} of its inputs, not the soundness of its logic. \\emph{SICA-specific}: under source-attribution scoring, SICA reduces to majority vote (Observation~1), and 27 training-free variants fail to escape. \\emph{General}: the DPI bound applies to any deterministic self-extraction, and symbolic confirmation bias---a persistent empirical pattern across all tested zero-shot self-extraction conditions, not a cognitive bias analogy---holds across nine models (7B to frontier), suggesting the bottleneck is intrinsic to self-referential constraint generation. Three diagnostics ($K_\\text{eff}$, BR, $C_0$) correctly characterize failure modes across all tested conditions, with boundaries generalizing to held-out families (\\S\\ref{sec:diagnostic-framework}).\n\n\\looseness=-1\nThese results connect to ensemble diversity theory \\citep{dietterich2000ensemble, krogh1994neural}: with $K_\\text{eff} \\leq 3.62$ for $K{=}12$, same-model traces scale redundancy, not information. For test-time compute scaling \\citep{snell2025scaling}, increasing $K$ within a single model yields diminishing returns when traces share systematic biases.\n\n\\looseness=-1\nEscaping the bottleneck requires structural independence (\\S\\ref{sec:cross-arch}); cross-architecture NLI provides a proof of concept, but whether trained extractors or hybrid approaches can shift the boundary remains open. Our diagnostic framework offers a concrete tool: a $K{=}12$ pilot run with three zero-cost metrics predicts whether any self-extraction method will help before full deployment.\n",
      "numLines": 13,
      "startLine": 1,
      "totalLines": 13
    }
  },
  "sourceToolAssistantUUID": "2ddea886-a82d-4c02-b11c-40177412f781",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 32 · 2026-05-24T04:28:34.911Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LXpT6BrnJqkkGR3vt2XyLZ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/limitations_content.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "afdf4375-71de-49c5-9ff4-5ec5f464d954",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "0a5ff2e2-009c-4324-9d20-ca670273700f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 33 · 2026-05-24T04:28:34.917Z_

<details><summary>↩ Tool result · `toolu_01LXpT6BrnJqkkGR3vt2XyLZ`</summary>

```text
1	\looseness=-1 \textbf{Model scale.} Our locally-run models range from 7B to 32B; frontier coverage (gpt-4o, gpt-4.1, gpt-5.5, o3, Gemini-2.5-Pro) relies on cross-model extraction rather than self-extraction, so we cannot confirm that self-extraction produces identical SCB patterns at frontier scale.
2	
3	\looseness=-1 \textbf{Domain scope.} All benchmarks are English logical reasoning. FOLIO and ProofWriter represent a best-case scenario for symbolic verification: problems are designed to have clean first-order logic representations, so the observed bias ratios ($1.66$--$4.97\times$) likely represent a \emph{lower bound} on SCB in less structured domains. We excluded GSM8K and AIME because $C_0 < 5\%$ made SICA degenerate by design; whether symbolic confirmation bias manifests differently in mathematical reasoning with higher extraction rates remains untested.
4	
5	\looseness=-1 \textbf{Statistical power and escape scope.} Statistical power is limited for effects below ${\sim}$2\,pp (MDE 1.86--4.84\,pp across conditions); small positive effects cannot be ruled out. The capability-gap analysis rests on $n{=}6$ rank-correlation conditions (Appendix~\ref{app:limitations-extended}). Multi-seed replication uses 3--4 seeds per model; cross-seed correlation is not modeled, and a larger seed budget could tighten the variance estimates. We do not evaluate trained extractors, which could potentially break the self-extraction bound by introducing external signal.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0a5ff2e2-009c-4324-9d20-ca670273700f",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "55ff56ed-dac3-42c0-94c0-aa597ee46a88",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/limitations_content.tex",
      "content": "\\looseness=-1 \\textbf{Model scale.} Our locally-run models range from 7B to 32B; frontier coverage (gpt-4o, gpt-4.1, gpt-5.5, o3, Gemini-2.5-Pro) relies on cross-model extraction rather than self-extraction, so we cannot confirm that self-extraction produces identical SCB patterns at frontier scale.\n\n\\looseness=-1 \\textbf{Domain scope.} All benchmarks are English logical reasoning. FOLIO and ProofWriter represent a best-case scenario for symbolic verification: problems are designed to have clean first-order logic representations, so the observed bias ratios ($1.66$--$4.97\\times$) likely represent a \\emph{lower bound} on SCB in less structured domains. We excluded GSM8K and AIME because $C_0 < 5\\%$ made SICA degenerate by design; whether symbolic confirmation bias manifests differently in mathematical reasoning with higher extraction rates remains untested.\n\n\\looseness=-1 \\textbf{Statistical power and escape scope.} Statistical power is limited for effects below ${\\sim}$2\\,pp (MDE 1.86--4.84\\,pp across conditions); small positive effects cannot be ruled out. The capability-gap analysis rests on $n{=}6$ rank-correlation conditions (Appendix~\\ref{app:limitations-extended}). Multi-seed replication uses 3--4 seeds per model; cross-seed correlation is not modeled, and a larger seed budget could tighten the variance estimates. We do not evaluate trained extractors, which could potentially break the self-extraction bound by introducing external signal.\n",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  },
  "sourceToolAssistantUUID": "0a5ff2e2-009c-4324-9d20-ca670273700f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 34 · 2026-05-24T04:28:35.490Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Mgzgck33ru78G1fT6ZAP8t`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "55ff56ed-dac3-42c0-94c0-aa597ee46a88",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "62921f5e-0904-4524-9b31-e3755d4d1034",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 35 · 2026-05-24T04:28:35.495Z_

<details><summary>↩ Tool result · `toolu_01Mgzgck33ru78G1fT6ZAP8t`</summary>

```text
1	\vspace{-2mm}
2	\section{Conclusion}\label{sec:conclusion}
3	
4	\looseness=-1 We identify symbolic confirmation bias: self-extracted constraints inherit the generating model's biases ($\text{BR} = 4.97\times$, 83.3\%), explaining why twenty-seven remediation strategies fail. Oracle controls ($+29.90$/$+13.73$\,pp) confirm the mechanism is sound; the bottleneck is extraction quality, not the formal channel. Three diagnostics predict failure ($C_0 < 5\%$, SC $\leq 40\%$, process similarity). Cross-architecture NLI escapes the bias: zero-shot gains for the weakest generator ($p < 0.001$); domain adaptation extends to generators with SC up to 72\%. DRC recovers 83--90\% of full-combo gain at 35--39\% cost.
5	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "62921f5e-0904-4524-9b31-e3755d4d1034",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "d65960d5-beb1-4e1b-9c30-3f711799865f",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/conclusion.tex",
      "content": "\\vspace{-2mm}\n\\section{Conclusion}\\label{sec:conclusion}\n\n\\looseness=-1 We identify symbolic confirmation bias: self-extracted constraints inherit the generating model's biases ($\\text{BR} = 4.97\\times$, 83.3\\%), explaining why twenty-seven remediation strategies fail. Oracle controls ($+29.90$/$+13.73$\\,pp) confirm the mechanism is sound; the bottleneck is extraction quality, not the formal channel. Three diagnostics predict failure ($C_0 < 5\\%$, SC $\\leq 40\\%$, process similarity). Cross-architecture NLI escapes the bias: zero-shot gains for the weakest generator ($p < 0.001$); domain adaptation extends to generators with SC up to 72\\%. DRC recovers 83--90\\% of full-combo gain at 35--39\\% cost.\n",
      "numLines": 5,
      "startLine": 1,
      "totalLines": 5
    }
  },
  "sourceToolAssistantUUID": "62921f5e-0904-4524-9b31-e3755d4d1034",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 36 · 2026-05-24T04:28:35.871Z_

<details open><summary>🔧 Tool call — Read · `toolu_011138oTBEEwk1zQXFN5ZTHC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d65960d5-beb1-4e1b-9c30-3f711799865f",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "775354f0-ae8a-45ca-a40b-1b208bbc94cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 37 · 2026-05-24T04:28:36.198Z_

<details><summary>↩ Tool result · reported error · `toolu_011138oTBEEwk1zQXFN5ZTHC`</summary>

```text
File content (38819 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "775354f0-ae8a-45ca-a40b-1b208bbc94cf",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "9f5ce6c4-0b24-4958-873e-197591b55150",
  "toolUseResult": "Error: File content (38819 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "775354f0-ae8a-45ca-a40b-1b208bbc94cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 38 · 2026-05-24T04:28:36.210Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RW5tfk8GKcdGAXAnhGg9sK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9f5ce6c4-0b24-4958-873e-197591b55150",
  "isSidechain": false,
  "requestId": "req_011CbLmCJVhyanUDzyMMVgs3",
  "type": "assistant",
  "uuid": "2d81bdd4-04f1-4017-a174-42b70bc00faf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DmwEg45x8BG7h5w2ianASx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 929,
      "cache_read_input_tokens": 24862,
      "output_tokens": 1015,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 929,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1015,
          "cache_read_input_tokens": 24862,
          "cache_creation_input_tokens": 929,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 929
          },
          "type": "message"
        }
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

_source line 39 · 2026-05-24T04:28:36.306Z_

```json
{
  "parentUuid": "e25538cb-68a3-432c-856c-f837f7b10cc8",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "13bfb00f-2324-4590-a882-85932b9cdae6",
  "timestamp": "2026-05-24T04:28:36.306Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---


### Runtime record

_source line 40_

```json
{
  "type": "last-prompt",
  "leafUuid": "13bfb00f-2324-4590-a882-85932b9cdae6",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Runtime record

_source line 41_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper numerics before submission deadline",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Assistant

_source line 42 · 2026-05-24T04:28:45.178Z_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the appendix (it's large), the cross_arch.tex file, and the figure generation scripts. I also need to extract the registry data. Let me read the appendix in chunks and the figure scripts.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "13bfb00f-2324-4590-a882-85932b9cdae6",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "0c3dc1be-60be-4db4-8c93-9f2e8c05977b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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

_source line 43 · 2026-05-24T04:28:46.438Z_

Now reading appendix in chunks, figure scripts, and extracting registry data.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0c3dc1be-60be-4db4-8c93-9f2e8c05977b",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "9903b640-4f7e-4315-a7a4-05846b01cfc8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-24T04:28:47.936Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CJgn5nE6mZm3dh1pFrGd15`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
  "limit": 500
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9903b640-4f7e-4315-a7a4-05846b01cfc8",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "560cfe60-01dc-4f3f-8157-ac33fff6a79d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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

_source line 45 · 2026-05-24T04:28:48.196Z_

<details><summary>↩ Tool result · `toolu_01CJgn5nE6mZm3dh1pFrGd15`</summary>

```text
1	\section{Prompt Templates}
2	\label{app:prompts}
3	
4	SICA uses domain-specific prompt templates for constraint extraction: one for mathematical reasoning (GSM8K, AIME) and one for logical reasoning (ProofWriter, FOLIO). Both share the same system prompt. The LLM is called with temperature $T{=}0.3$, max tokens $1024$, and structured JSON output mode. Up to 6 traces are processed in parallel via thread pooling, with 2 retries on failure (exponential backoff, base 0.5s).
5	
6	\paragraph{System Prompt.}
7	
8	\begin{lstlisting}
9	You are a constraint extraction tool. Output ONLY
10	valid JSON. Do NOT solve problems, reason about
11	correctness, or think step-by-step. Extract
12	constraints from the given trace exactly as stated.
13	\end{lstlisting}
14	
15	\paragraph{Mathematical Constraint Extraction (EXTRACTION\_PROMPT).}
16	
17	Used for GSM8K and AIME datasets. The placeholder \texttt{\{trace\}} is replaced with the reasoning trace at runtime.
18	
19	\begin{lstlisting}
20	Extract mathematical constraints from this reasoning
21	trace as a JSON object.
22	
23	Rules:
24	- type: "equation", "inequality", or "predicate"
25	- expression: human-readable, e.g. "x + y == 14"
26	- z3_formula: a single comparison expression in
27	  Python Z3 syntax
28	- source_step: step number where the constraint
29	  appears
30	- Use variable names from the trace
31	
32	z3_formula MUST follow these rules:
33	- Allowed operators: ==, !=, <, >, <=, >=, +, -, *,
34	  /, **, %
35	- Use individual named variables: a1, a2, a3...
36	  NOT arrays a[1] or sets A
37	- Expand all sums explicitly:
38	  "a1 + a2 + a3 == 55" NOT "sum([a1,a2,a3])"
39	- NO Python builtins: sum(), len(), max(), min(),
40	  list(), set(), range(), int()
41	- Each z3_formula must be exactly ONE comparison
42	  (==, !=, <, >, <=, >=)
43	- For multiple values, write separate constraints
44	  for each
45	
46	Output ONLY the JSON below, nothing else:
47	{"constraints": [{"type": "equation",
48	  "expression": "x + y == 14",
49	  "z3_formula": "x + y == 14",
50	  "source_step": 1}],
51	 "answer": "final_answer",
52	 "variables": ["x", "y"]}
53	
54	Trace:
55	{trace}
56	\end{lstlisting}
57	
58	\paragraph{Logical Constraint Extraction (LOGIC\_EXTRACTION\_PROMPT).}
59	
60	Used for ProofWriter and FOLIO datasets.
61	
62	\begin{lstlisting}
63	IMPORTANT: You are an EXTRACTION tool, NOT a problem
64	solver.
65	- Do NOT re-solve or re-reason about the problem.
66	- Do NOT verify whether the trace's reasoning is
67	  correct.
68	- ONLY extract the logical constraints that are
69	  explicitly stated or used in the trace below.
70	- Output ONLY the JSON object, nothing else.
71	
72	Extract logical constraints from this reasoning trace
73	about a logic problem.
74	
75	The problem has facts (base assertions), rules
76	(grounded implications), and derived conclusions.
77	Convert each into a Z3 boolean formula.
78	
79	Variable naming:
80	- Unary property: property_entity
81	  (e.g., kind_anne, red_charlie, round_fiona)
82	- Binary relation: relation_subject_object
83	  (e.g., eats_bear_squirrel, likes_lion_cat)
84	- Use lowercase with underscores only
85	
86	Constraint types:
87	- "fact": a given assertion,
88	  e.g., kind_anne == True
89	- "rule": a grounded implication over specific
90	  entities, e.g., Implies(kind_anne, nice_anne)
91	- "derived": an inferred conclusion from facts +
92	  rules, e.g., nice_anne == True
93	
94	Z3 operators:
95	- Implies(a, b) for if-then rules
96	- And(a, b, ...) for conjunctive conditions
97	- Or(a, b, ...) for disjunctive conditions
98	- Not(a) for negation
99	- == True / == False for boolean assertions
100	
101	Output ONLY the JSON below, nothing else:
102	{"constraints": [{"type": "fact",
103	  "expression": "kind(anne)",
104	  "z3_formula": "kind_anne == True",
105	  "source_step": 1}],
106	 "answer": "True or False or Unknown",
107	 "variables": ["kind_anne"]}
108	
109	Trace:
110	{trace}
111	\end{lstlisting}
112	
113	\paragraph{Output Schema.}
114	
115	Both prompts produce a JSON object with the following structure:
116	
117	\begin{lstlisting}
118	{
119	  "constraints": [
120	    {
121	      "type": "&lt;equation|inequality|predicate>
122	               or &lt;fact|rule|derived>",
123	      "expression": "&lt;human-readable description>",
124	      "z3_formula": "&lt;Z3-compatible expression>",
125	      "source_step": &lt;integer>
126	    }
127	  ],
128	  "answer": "&lt;final answer string>",
129	  "variables": ["&lt;var1>", "&lt;var2>", "..."]
130	}
131	\end{lstlisting}
132	
133	The pipeline additionally injects an \texttt{answer\_assertion} constraint per trace (not produced by the LLM):
134	
135	\begin{lstlisting}
136	{"type": "answer_assertion",
137	 "expression": "answer is &lt;ans>",
138	 "z3_formula": "__sica_answer_&lt;ans> == True",
139	 "source_step": -1}
140	\end{lstlisting}
141	
142	\paragraph{Prompt Selection Logic.}
143	
144	Domain assignment is determined by dataset: FOLIO and ProofWriter use \textsc{Logic\_Extraction\_Prompt}; GSM8K, AIME, StrategyQA, and ARC-Challenge use \textsc{Extraction\_Prompt}. StrategyQA and ARC-Challenge are assigned to the mathematical prompt because their reasoning structure does not involve formal logic predicates or implications, despite StrategyQA producing boolean answers.
145	
146	
147	\section{Z3 MaxSAT Evaluation Pseudocode}
148	\label{app:z3-pseudocode}
149	
150	Algorithm~\ref{alg:maxsat} describes the Z3 MaxSAT solving procedure. Algorithm~\ref{alg:scorer} describes the source-trace attribution scoring.
151	
152	Domain constraint variables (e.g., \texttt{x + y == 14}) and answer assertion variables (e.g., \texttt{\_\_sica\_answer\_42 == True}) are logically independent in the Z3 formulation. Discriminative signal arises solely from conflicts among domain constraints: when traces supporting different answers produce mutually contradictory constraints, the solver excludes the lower-weight subset, and the scorer penalizes the corresponding answers.
153	
154	\begin{algorithm}[h]
155	\caption{Z3 Weighted Partial MAX-SAT}
156	\label{alg:maxsat}
157	\begin{algorithmic}[1]
158	\Require Deduplicated constraint set $\mathcal{C} = \{(c_m, w_m, S_m)\}_{m=1}^M$ where $c_m$ is a Z3 formula, $w_m$ is weight, $S_m$ is the set of source trace indices
159	\Ensure Partition $(\mathcal{C}^*, \mathcal{C}^{\setminus})$ where $\mathcal{C}^*$ is the max-weight satisfiable subset
160	\State $\textit{opt} \gets \textsc{Z3.Optimize()}$
161	\For{$m = 1, \ldots, M$}
162	    \State $b_m \gets$ fresh Boolean indicator
163	    \State $\textit{opt}.\textsc{Add}(b_m \Rightarrow c_m)$ \Comment{soft clause guarded by indicator}
164	    \State $\textit{opt}.\textsc{AddSoft}(b_m,\; \text{weight}=w_m)$
165	\EndFor
166	\State $\textit{result} \gets \textit{opt}.\textsc{Check}()$
167	\State $\textit{model} \gets \textit{opt}.\textsc{Model}()$
168	\State $\mathcal{C}^* \gets \{(c_m, w_m, S_m) : \textit{model}(b_m) = \top\}$
169	\State $\mathcal{C}^{\setminus} \gets \mathcal{C} \setminus \mathcal{C}^*$
170	\State \Return $(\mathcal{C}^*, \mathcal{C}^{\setminus})$
171	\end{algorithmic}
172	\end{algorithm}
173	
174	\begin{algorithm}[h]
175	\caption{Source-Trace Attribution Scoring}
176	\label{alg:scorer}
177	\begin{algorithmic}[1]
178	\Require Satisfied set $\mathcal{C}^*$, excluded set $\mathcal{C}^{\setminus}$, candidate answers $\mathcal{A}$, trace-answer mapping $\tau: \text{trace\_idx} \to a$, penalty weight $\alpha$
179	\Ensure Score $s(a)$ for each $a \in \mathcal{A}$
180	\For{each $a \in \mathcal{A}$}
181	    \State $T_a \gets \{i : \tau(i) = a\}$ \Comment{trace indices producing answer $a$}
182	    \State $\textit{pos}(a) \gets \sum_{(c,w,S) \in \mathcal{C}^*} w \cdot \mathbf{1}[S \cap T_a \neq \emptyset]$
183	    \State $\textit{neg}(a) \gets \sum_{(c,w,S) \in \mathcal{C}^{\setminus}} w \cdot \mathbf{1}[S \cap T_a \neq \emptyset]$
184	    \State $s(a) \gets \textit{pos}(a) - \alpha \cdot \textit{neg}(a)$
185	\EndFor
186	\State \Return $a^* = \arg\max_{a \in \mathcal{A}} s(a)$
187	\end{algorithmic}
188	\end{algorithm}
189	
190	
191	\section{Capability-Accuracy Constraint Diagnostics}
192	\label{app:diagnostics}
193	\label{app:cil}
194	
195	\paragraph{Conditional Correction Ratio.}
196	We define the \textit{Conditional Correction Ratio} (CCR) to summarize verifier--generator complementarity:
197	\begin{equation}
198	\label{eq:cil}
199	\text{CCR}(V, G) = \log \frac{P(V \text{ correct} \mid G \text{ wrong})}{P(V \text{ correct} \mid G \text{ correct})}.
200	\end{equation}
201	$\text{CCR} > 0$ means $V$ preferentially corrects $G$'s errors; $\text{CCR} < 0$ indicates shared bias. CCR links our findings: (1)~SCB corresponds to $\text{CCR}(\text{self}, G) \approx 0$; (2)~Finding~2 predicts $\text{CCR}(V, G) > 0$ when $V$ is independent and capable.
202	
203	\paragraph{Empirical CCR across verifier--generator pairs.}
204	Table~\ref{tab:cil_empirical} reports CCR for eight verifier--generator--dataset conditions, sorted by CCR descending. All three cross-architecture NLI pairs on ProofWriter yield $\text{CCR} > 0$ (verifier preferentially corrects generator errors), while all three same-model SICA conditions yield $\text{CCR} < 0$ (shared bias). CCR correlates with combo gain: Spearman $\rho = 0.839$, 95\% bootstrap CI $[0.338, 0.990]$; LOO-robust (min $p = 0.014$). Four of eight conditions share the DeBERTa verifier, yielding effective $n < 10$; results should be interpreted as a consistent pattern rather than a precise effect size.
205	
206	\begin{table}[h]
207	\centering
208	\small
209	\caption{Empirical CCR across eight verifier--generator conditions (sorted by CCR descending). $\text{CCR} > 0$: cross-architecture NLI verifiers on ProofWriter. $\text{CCR} < 0$: same-model SICA or mismatched capability gap.}
210	\label{tab:cil_empirical}
211	\resizebox{\columnwidth}{!}{%
212	\begin{tabular}{@{}lllrr@{}}
213	\toprule
214	Generator & Verifier & Dataset & CCR & $\Delta$ (pp) \\
215	\midrule
216	Mistral-7B & BART-MNLI & PW-600 & $+$1.86 & $+$5.17 \\
217	Mistral-7B & DeBERTa-MNLI & PW-600 & $+$1.67 & $+$6.67 \\
218	Mistral-7B & RoBERTa-MNLI & PW-600 & $+$1.42 & $+$4.17 \\
219	\addlinespace
220	Qwen2.5-14B & DeBERTa-MNLI & PW-600 & $-$0.21 & $+$0.33 \\
221	Mistral-7B & DeBERTa-MNLI & FOLIO-204 & $-$0.47 & $+$2.94 \\
222	\addlinespace
223	Mistral-7B & SICA & FOLIO-204 & $-$2.93 & $+$3.43 \\
224	Qwen2.5-14B & SICA & PW-600 & $-$4.21 & $-$2.50 \\
225	Mistral-7B & SICA & PW-600 & $-$4.61 & $-$2.83 \\
226	\bottomrule
227	\end{tabular}}
228	\end{table}
229	
230	\paragraph{Per-condition diagnostics.}
231	Table~\ref{tab:capability_trap} reports per-condition diagnostic metrics referenced in \S\ref{sec:entropy}.
232	
233	\begin{table}[h]
234	\centering
235	\small
236	\resizebox{\columnwidth}{!}{%
237	\begin{tabular}{@{}llrrrr@{}}
238	\toprule
239	Model & Domain & $C_0$ (\%) & Extr.\ Rate & Contr.\ Rate & $\Delta$ (pp) \\
240	\midrule
241	Qwen2.5-14B & FOLIO & 35.3 & 0.89 & 0.022 & 0.00 \\
242	Qwen2.5-14B & ProofWriter & 39.2 & 0.89 & 0.022 & $+$0.33 \\
243	Qwen2.5-14B & StrategyQA$^\dagger$ & 10.0 & 0.70 & --- & $+$3.33 \\
244	Qwen2.5-14B & ARC-Chall.$^\dagger$ & 5.0 & 1.00 & --- & $-$1.67 \\
245	Qwen2.5-7B & FOLIO+PW$^\dagger$ & 42.1 & 0.94 & 0.027 & 0.00 \\
246	Mistral-7B & FOLIO+PW$^\dagger$ & 50.0 & 0.88 & 0.056 & 0.00 \\
247	LLaMA-3.1-8B & StrategyQA & 41.0 & --- & --- & $+$2.00 \\
248	LLaMA-3.1-8B & FOLIO & 61.8 & 0.94 & 0.062 & $-$4.41 \\
249	DeepSeek-R1-7B & FOLIO+PW$^\dagger$ & 58.3 & 0.84 & 0.037 & $-$3.33 \\
250	QwQ-32B & Combined$^\dagger$ & 2.6 & --- & --- & 0.00 \\
251	Qwen2.5-14B & GSM8K$^\dagger$ & 13.3 & 0.15 & --- & 0.00 \\
252	\bottomrule
253	\end{tabular}}
254	\caption{Capability-accuracy constraint diagnostics. $C_0$: fraction of questions with multiple distinct candidate answers across $K=12$ traces. Extraction rate: fraction of traces yielding at least one parseable logical constraint. Contradiction rate: fraction of extracted constraint sets with internal contradictions. $\Delta$: SICA$-$SC gap (pp). $\dagger$: $n \leq 60$. Dashes indicate conditions where extraction diagnostics were not computed (StrategyQA uses boolean answers without symbolic extraction; QwQ-32B Combined had near-zero $C_0$, making extraction analysis uninformative). This table includes additional exploratory conditions not reported in Table~\ref{tab:main_results}.}
255	\label{tab:capability_trap}
256	\end{table}
257	
258	
259	\section{Statistical Power Analysis}
260	\label{app:power}
261	
262	We compute the minimum detectable effect (MDE) for each condition at $\alpha = 0.05$ and 80\% power using exact binomial power calculations over McNemar discordant pairs. Table~\ref{tab:power} reports three grouped conditions with $n \geq 200$ (Qwen2.5-14B FOLIO and ProofWriter are pooled into a single $n{=}804$ analysis, corresponding to four Table~\ref{tab:main_results} rows), which constitute our confirmatory analyses. The remaining seven conditions ($n \leq 60$) yield infinite MDE due to insufficient discordant pairs and serve only as regime characterization.
263	
264	\begin{table}[h]
265	\centering
266	\small
267	\resizebox{\columnwidth}{!}{%
268	\begin{tabular}{lrrrrr}
269	\toprule
270	\textbf{Condition} & $n$ & \textbf{MDE} & \textbf{Obs.\ $\Delta$} & \textbf{Obs.\ Pow.} \\
271	\midrule
272	Qwen-14B FOLIO+PW   & 804 & 1.86pp & $+$0.25pp & 5.7\%  \\
273	LLaMA-8B StrategyQA  & 200 & 4.64pp & $+$2.00pp & 20.6\% \\
274	LLaMA-8B FOLIO       & 204 & 4.84pp & $-$4.41pp & 18.6\% \\
275	\bottomrule
276	\end{tabular}}
277	\caption{Power analysis for confirmatory conditions ($n \geq 200$). MDE = minimum detectable effect at 80\% power. All observed effects fall below their respective MDEs, and observed power remains below 21\% in every case.}
278	\label{tab:power}
279	\end{table}
280	
281	The largest study (Qwen-14B, $n{=}804$, 30 discordant pairs) can detect effects as small as 1.86pp, yet the observed $\Delta$ of $+$0.25pp is an order of magnitude smaller. The two LLaMA-8B conditions require effects of 4.64pp and 4.84pp to reach significance; neither observed $\Delta$ approaches these thresholds. All three conditions are consistent with the null hypothesis that SICA provides no accuracy gain over self-consistency.
282	
283	
284	\section{Bootstrap Confidence Intervals}
285	\label{app:bootstrap}
286	
287	We compute 95\% confidence intervals for $\Delta(\text{SICA} - \text{SC})$ via 10{,}000 bootstrap resamples (percentile method, seed 42). Table~\ref{tab:bootstrap} reports the results for the three confirmatory conditions.
288	
289	\begin{table}[h]
290	\centering
291	\small
292	\resizebox{\columnwidth}{!}{%
293	\begin{tabular}{lrrl}
294	\toprule
295	\textbf{Condition} & $n$ & \textbf{Obs.\ $\Delta$} & \textbf{95\% CI} \\
296	\midrule
297	Qwen-14B FOLIO+PW   & 804 & $+$0.25pp & [$-$1.12, $+$1.62] \\
298	LLaMA-8B StrategyQA  & 200 & $+$2.00pp & [$-$1.50, $+$5.50] \\
299	LLaMA-8B FOLIO       & 204 & $-$4.41pp & [$-$5.88, $+$0.98] \\
300	\bottomrule
301	\end{tabular}}
302	\caption{Bootstrap 95\% confidence intervals for $\Delta(\text{SICA} - \text{SC})$ in percentage points. All intervals include zero, consistent with no reliable accuracy difference.}
303	\label{tab:bootstrap}
304	\end{table}
305	
306	All three intervals contain zero. The narrowest interval (Qwen-14B, [$-$1.12, $+$1.62]) rules out practically meaningful gains ($>$2pp) even in the most favorable case. The widest interval (LLaMA-8B FOLIO, [$-$5.88, $+$0.98]) skews negative, indicating that SICA may slightly hurt accuracy in this condition. These results corroborate the McNemar tests and power analysis: no condition provides evidence that logical constraint aggregation improves over majority voting.
307	
308	
309	\section{Case Studies: Discordant Predictions}
310	\label{app:case-studies}
311	
312	Among 804 problems, SICA and SC agree on 773 (96.1\%). The 31 discordant cases comprise 16 SICA wins (SICA correct, SC wrong), 14 SC wins (SC correct, SICA wrong), and 1 where both select different wrong answers. All 31 occur at exact ties (entropy${=}1.0$, 6:6 vote split) or near-ties (entropy${\geq}0.9183$, 8:4 at most), since SICA can differ from SC only when constraint weights shift the majority away from SC's tiebreak choice. We present three representative cases that illustrate the mechanism behind capability-accuracy constraint failures.
313	
314	\paragraph{Case 1: SICA Wins (folio\_134, FOLIO).}
315	
316	\emph{Premises}: Some mammals have teeth. Platypus have no teeth. Platypus are mammals. Humans have teeth. \emph{Conclusion}: Humans are mammals. \emph{Gold}: Unknown.
317	
318	The premises state that \emph{some} mammals have teeth and that humans have teeth, but ``having teeth'' is not sufficient for ``being a mammal'' under open-world semantics. SC produces a 6:6 split (Unknown:6, True:6) and tiebreaks alphabetically to True (wrong). SICA extracts 7 constraints; MaxSAT excludes 1 constraint inconsistent with the rest, reducing the weighted score for True-voting traces and tipping the aggregation to Unknown (correct). The excluded constraint likely captured an incorrect inference step (e.g., affirming the consequent) present only in True-voting traces. While SICA succeeds here, the success is coincidental: the excluded constraint happens to anti-correlate with the correct answer.
319	
320	\paragraph{Case 2: SC Wins (ProofWriter-1066\_Q6, ProofWriter).}
321	
322	\emph{Key chain}: White(Bob)$\to$Round(Bob) [white things are round] $\to$ Young(Bob) [all round things are young]. \emph{Conclusion}: ``Bob is not young.'' \emph{Gold}: False (Bob IS young).
323	
324	SC produces a 6:6 split (False:6, True:6) and tiebreaks to False (correct). SICA extracts 17 constraints; MaxSAT excludes 2 that appear preferentially in False-voting traces. These excluded constraints likely captured correct intermediate derivations (e.g., \texttt{young\_bob == True}) that appeared only in traces completing the full deduction chain. By excluding them, MaxSAT removes evidence supporting the correct answer. SICA selects True (wrong). This case illustrates how self-extracted constraints can systematically mislead: correct reasoning steps become discriminative signals that the solver mistakenly penalizes.
325	
326	\paragraph{Case 3: Non-discriminative Constraints (ProofWriter-903\_Q6, ProofWriter).}
327	
328	\emph{Key chain}: Nice(Mouse)$\to$Cold(Mouse) [all nice people are cold] $\to$ Chases(Mouse,Mouse) [nice and cold $\to$ chase mouse]. \emph{Conclusion}: ``The mouse does not chase the mouse.'' \emph{Gold}: False.
329	
330	SC produces a 6:6 split (False:6, Unknown:6) and tiebreaks to False (correct). SICA extracts 44 constraints but excludes only 1 (2.3\%). The remaining 43 are domain facts and grounded rules (\texttt{nice\_mouse == True}, \texttt{Implies(nice\_mouse, cold\_mouse)}, etc.) that Z3 satisfies identically regardless of the final answer. Both False-voting and Unknown-voting traces share the same premises and grounded rules; they differ only in whether the trace completed the full derivation chain. The single excluded constraint carries negligible weight against 43 shared constraints, so SICA collapses to SC.
331	
332	\paragraph{Pattern.}
333	
334	These cases exemplify the general pattern across the 773 agreeing problems: the vast majority of extracted constraints encode shared domain structure rather than answer-specific reasoning, and MaxSAT aggregation degenerates to majority vote. Table~\ref{tab:case_summary} summarizes.
335	
336	\begin{table}[h]
337	\centering
338	\small
339	\caption{Summary of three representative discordant cases. All occur at exact 6:6 vote ties. Constraint exclusion can break ties in either direction (Cases 1--2) or have no effect (Case 3).}
340	\label{tab:case_summary}
341	\resizebox{\columnwidth}{!}{%
342	\begin{tabular}{@{}lllcccc@{}}
343	\toprule
344	Case & ID & Gold & SC & SICA & \#Constr. & Excl.\ (\%) \\
345	\midrule
346	1 (SICA win) & folio\_134 & Unknown & True $\times$ & Unknown $\checkmark$ & 7 & 1 (14.3\%) \\
347	2 (SC win) & PW-1066\_Q6 & False & False $\checkmark$ & True $\times$ & 17 & 2 (11.8\%) \\
348	3 (Non-disc.) & PW-903\_Q6 & False & False $\checkmark$ & False $\checkmark$ & 44 & 1 (2.3\%) \\
349	\bottomrule
350	\end{tabular}}
351	\end{table}
352	
353	
354	\section{Oracle Control}
355	\label{app:oracle}
356	\label{sec:oracle}
357	\label{app:pw-oracle-subtype}
358	
359	Replacing self-extracted constraints with gold annotations (FOLIO logical formulae, ProofWriter DSL), Oracle-SICA yields $+29.90$\,pp on Mistral-7B FOLIO ($p < 10^{-13}$), $+13.73$\,pp on Qwen2.5-14B FOLIO ($p = 2.0 \times 10^{-7}$), and $+17.17$\,pp on ProofWriter ($p < 10^{-14}$). Z3 agrees with gold labels on 95.1\% (FOLIO) and 97.1\% (ProofWriter). The MAX-SAT mechanism is sound; Mistral-7B's best self-extracted $\Delta$ ($+3.43$\,pp) captures only 11.5\% of its oracle ceiling. For Qwen2.5-14B on ProofWriter, the gap is wider still: self-extraction degrades accuracy ($-2.50$\,pp) against an oracle ceiling of $+17.17$\,pp, indicating that stronger models do not self-extract more effectively.
360	
361	\paragraph{ProofWriter per-subtype analysis.} ProofWriter problems encode deductive rules as Domain-Specific Language (DSL) logic programs. Each problem uses one of four predicate subtypes: attribute predicates with or without negation (AttNeg, AttNoneg), and relation predicates with or without negation (RelNeg, RelNoneg). Relation predicates involve binary relations between entities (e.g., \texttt{eats(bear, squirrel)}), while attribute predicates assign unary properties (e.g., \texttt{kind(anne)}).
362	
363	The oracle pipeline parses these DSL annotations deterministically into Z3 formulas without any LLM involvement. Of the 600 ProofWriter problems, 594 (99.0\%) produce valid Z3 parses; the remaining 6 fail due to unsupported DSL constructs. Across all 7{,}128 trace-problem pairs submitted to Z3, the solver returns a result in every case (0\% solver errors). Z3 evaluations agree with ground-truth labels on 577 of 594 parseable problems (97.14\%), confirming that the deterministic DSL-to-Z3 translation faithfully preserves problem semantics.
364	
365	Table~\ref{tab:pw_oracle_subtype} reports the per-subtype breakdown. Relation-predicate subtypes show substantially larger gains than attribute-predicate subtypes: RelNeg improves by $+28.58$~pp and RelNoneg by $+23.29$~pp, compared to $+10.00$~pp for AttNeg and $+8.44$~pp for AttNoneg. Relation predicates involve longer reasoning chains with more intermediate entities, producing greater answer diversity across traces ($C_0$) and more opportunities for oracle constraints to correct errors.
366	
367	\begin{table}[h]
368	\centering
369	\caption{ProofWriter oracle experiment per-subtype breakdown. Oracle-SICA uses gold DSL annotations parsed deterministically to Z3 for consistency checking. Relation-predicate subtypes (RelNeg, RelNoneg) show larger gains than attribute-predicate subtypes; relation subtypes involve longer reasoning chains and benefit more from oracle constraints. Bold indicates best accuracy per row.}
370	\label{tab:pw_oracle_subtype}
371	\resizebox{\columnwidth}{!}{%
372	\begin{tabular}{lcccc}
373	\toprule
374	Subtype & $n$ & SC Acc (\%) & Oracle Acc (\%) & $\Delta$ (pp) \\
375	\midrule
376	AttNoneg & 154 & 90.26 & \textbf{98.70} & +8.44 \\
377	AttNeg & 160 & 81.88 & \textbf{91.88} & +10.00 \\
378	RelNoneg & 146 & 60.96 & \textbf{84.25} & +23.29 \\
379	RelNeg & 140 & 60.71 & \textbf{89.29} & +28.58 \\
380	\midrule
381	Overall & 600 & 74.00 & \textbf{91.17} & +17.17 \\
382	\bottomrule
383	\end{tabular}}
384	\end{table}
385	
386	
387	\section{Constraint Ablation Details}
388	\label{app:ablation}
389	\label{sec:ablation}
390	
391	\begin{table}[h]
392	\centering
393	\small
394	\caption{Constraint ablation (Qwen2.5-14B, $n = 804$). Agreement: predictions identical to SC. MAX-SAT and count-only produce nearly identical predictions, confirming that self-extracted constraints carry no signal beyond vote counts.}
395	\label{tab:ablation}
396	\begin{tabular}{@{}lrc@{}}
397	\toprule
398	Aggregation & Acc.\ (\%) & Agreement w/ SC \\
399	\midrule
400	SC (majority vote) & 76.24 & --- \\
401	SICA (MAX-SAT) & 76.49 & 773\,/\,804 \\
402	Count-only & 76.62 & 774\,/\,804 \\
403	Random-weight & 75.87 & 764\,/\,804 \\
404	\bottomrule
405	\end{tabular}
406	\end{table}
407	
408	\begin{table}[h]
409	\centering
410	\small
411	\caption{MAX-SAT vs.\ count-only agreement across constraint weight $\alpha \in [0,1]$ on FOLIO ($n = 204$). Mistral-7B (BR $= 4.97\times$, seed 42); Qwen2.5-14B (BR $= 3.85\times$, seed 123). $\alpha{=}0$: pure Z3 satisfiability (no source-attribution); $\alpha{=}1$: full source-attribution penalty. Agreement $\geq 99\%$ at all $\alpha$ including endpoints, confirming vacuity is weight-insensitive.}
412	\label{tab:alpha-ablation}
413	\begin{tabular}{@{}crr@{}}
414	\toprule
415	$\alpha$ & Mistral Agr.\ (\%) & Qwen2.5 Agr.\ (\%) \\
416	\midrule
417	0.0 & 100 & 100 \\
418	0.1 & 100 & 100 \\
419	0.3 & 100 & 100 \\
420	0.5 & 100 & 100 \\
421	0.7 & 99 & 100 \\
422	0.9 & 99 & 100 \\
423	1.0 & 99 & 100 \\
424	\bottomrule
425	\end{tabular}
426	\end{table}
427	
428	
429	\section{Remediation Strategy Details}
430	\label{app:remediation}
431	
432	\begin{table}[h]
433	\centering
434	\small
435	\caption{Nine prompt-level remediation strategies. Baseline: Qwen2.5-14B FOLIO, SC $= 75.98\%$, $\Delta = -0.49$\,pp. None reaches significance. Three method-level strategies are reported in Table~\ref{tab:method_interventions}.}
436	\label{tab:remediation}
437	\resizebox{\columnwidth}{!}{%
438	\begin{tabular}{@{}llrl@{}}
439	\toprule
440	Strategy & Target & $\Delta$ (pp) & Key finding \\
441	\midrule
442	Contrastive$^a$ & Prompt & $-$1.10 & non-disc.\ 6.0\% ($\downarrow$ from 8.2\%) \\
443	Cross-model$^b$ & Architecture & 0.00 & disc.\ 0\% (weak$\to$strong); $\pm$1\,pp (strong$\to$weak) \\
444	Qwen3-14B$^c$ & Capability & $-$0.49 & $p = 0.655$ \\
445	Z3 feedback & Solver & --- & 0.9\% UNSAT trigger \\
446	Cons.\ filtering & Noise & 0.00 & $T{\geq}4 \to$ SC \\
447	Cross-trace UNSAT & Independence & --- & 56.4\% $\emptyset$ vars \\
448	$T{=}1.0$$^d$ & Diversity & 0.00 & isolated peak at $T{=}0.7$ only \\
449	Multi-temp$^e$ & Diversity & 0.00 & $b{=}5$, $c{=}5$ (balanced) \\
450	Disc.\ filtering$^f$ & Filtering & 0.00 & 803/804 agree w/ SICA \\
451	\bottomrule
452	\end{tabular}}\\[2pt]
453	{\footnotesize $^a$\,$n{=}182$ (extraction failures excluded). $^b$\,Weak$\to$strong: Mistral-7B extracts from Qwen2.5-14B traces. Strong$\to$weak: Qwen3-14B (60.29\%) and Qwen2.5-14B (58.33\%) extract from Mistral-7B FOLIO traces ($n{=}204$); self-extraction baseline 59.31\%. $^c$\,$n{=}204$, SC $= 83.33\%$. $^d$\,Mistral-7B FOLIO, $n{=}204$. $^e$\,Mistral-7B FOLIO, $T \in \{0.3, 0.7, 1.2\}$, 4 traces each, $n{=}204$. $^f$\,Qwen2.5-14B, $n{=}804$; removing non-discriminative constraints.}
454	\end{table}
455	
456	
457	\begin{table}[h]
458	\centering
459	\small
460	\caption{Method-level interventions on Mistral-7B with McNemar's paired test. All produce neutral-to-catastrophic results. ICG shows two FOLIO seeds; $p$ for the first. {*}{*}{*}\,$p < 0.001$; {*}{*}\,$p < 0.01$.}
461	\label{tab:method_interventions}
462	\resizebox{\columnwidth}{!}{%
463	\begin{tabular}{@{}ll rc rc@{}}
464	\toprule
465	& & \multicolumn{2}{c}{FOLIO ($n = 204$)} & \multicolumn{2}{c}{LogiQA ($n = 200$)} \\
466	\cmidrule(lr){3-4} \cmidrule(lr){5-6}
467	Method & Target & $\Delta$ (pp) & $p$ & $\Delta$ (pp) & $p$ \\
468	\midrule
469	SC baseline & --- & 0.00 & --- & 0.00 & --- \\
470	ICG & Trace coupling & $-$1.96\,/\,$+$1.47 & .206 & $-$0.50 & .706 \\
471	Contrastive & Scoring bias & $\mathbf{-9.31}$ & .007 & $-$4.50 & .160 \\
472	Debate & Role diversity & $\mathbf{-18.63}$ & ${<}.001$ & $\mathbf{-23.00}$ & ${<}.001$ \\
473	\bottomrule
474	\end{tabular}}
475	\end{table}
476	
477	\section{Additional Intervention Results}
478	\label{app:additional-interventions}
479	
480	\begin{table*}[h]
481	\centering
482	\small
483	\caption{Additional intervention results beyond the nine prompt-level and three method-level strategies reported in the main text. All produce neutral-to-negative results, completing the exhaustive remediation analysis across 27 distinct approaches.}
484	\label{tab:additional_interventions}
485	\begin{tabular}{@{}llllrl@{}}
486	\toprule
487	\# & Method & Type & Target & $\Delta$ (pp) & Key Finding \\
488	\midrule
489	13 & PROVE (code verif.) & Paradigm & Formal proof & $-$1.9 & 15.2\% compilable; conclusive acc.\ = 50\% \\
490	14 & CEGIS (iterative) & Multi-round & Consistency & 0.0$^\dagger$ & R1 $+$3.43\,pp then oscillates \\
491	15 & DeepConf (logprob) & Filtering & Confidence & 0.0 & $\Delta_{\text{logprob}} = 0.006$ (no separation) \\
492	16 & Cross-model SICA & Cross-model & Independence & $-$0.49 & $\kappa_{\text{cross}}{=}0.42$ vs $\kappa_{\text{within}}{=}0.53$ \\
493	17 & Problem perturbation & Input diversity & Trace diversity & $<$0 & $\kappa$ \emph{increased} to 0.70 (anti-effect) \\
494	18 & MIN-UNSAT & Solver objective & Constraint sel.\ & $-$6.5 & Mean excluded constraints $= 1.3$ \\
495	19 & $\kappa$-aware SC & Voting rule & Weighted voting & 0.0 & 11/11 conditions $\Delta = 0$ \\
496	20 & Z3 trace filter & Trace filtering & Quality & $-$0.49 & Precision 49.1\%, 7 questions affected \\
497	21 & Bootstrapped gold & Iterative & Self-improvement & 0.0$^\dagger$ & R1 $+$2.45\,pp then oscillates \\
498	22 & Selective abstention & Diagnostic & Confidence & $+$4.4$^*$ & AUROC $= 0.673$, at 80\% coverage \\
499	23 & ASCII perturbation & Input diversity & Format diversity & 0.0 & $\kappa$: $0.39 \to 0.36$ (negligible) \\
500	\addlinespace
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "560cfe60-01dc-4f3f-8157-ac33fff6a79d",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "5d57b38d-6693-429b-8bf9-abc481de24de",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
      "content": "\\section{Prompt Templates}\n\\label{app:prompts}\n\nSICA uses domain-specific prompt templates for constraint extraction: one for mathematical reasoning (GSM8K, AIME) and one for logical reasoning (ProofWriter, FOLIO). Both share the same system prompt. The LLM is called with temperature $T{=}0.3$, max tokens $1024$, and structured JSON output mode. Up to 6 traces are processed in parallel via thread pooling, with 2 retries on failure (exponential backoff, base 0.5s).\n\n\\paragraph{System Prompt.}\n\n\\begin{lstlisting}\nYou are a constraint extraction tool. Output ONLY\nvalid JSON. Do NOT solve problems, reason about\ncorrectness, or think step-by-step. Extract\nconstraints from the given trace exactly as stated.\n\\end{lstlisting}\n\n\\paragraph{Mathematical Constraint Extraction (EXTRACTION\\_PROMPT).}\n\nUsed for GSM8K and AIME datasets. The placeholder \\texttt{\\{trace\\}} is replaced with the reasoning trace at runtime.\n\n\\begin{lstlisting}\nExtract mathematical constraints from this reasoning\ntrace as a JSON object.\n\nRules:\n- type: \"equation\", \"inequality\", or \"predicate\"\n- expression: human-readable, e.g. \"x + y == 14\"\n- z3_formula: a single comparison expression in\n  Python Z3 syntax\n- source_step: step number where the constraint\n  appears\n- Use variable names from the trace\n\nz3_formula MUST follow these rules:\n- Allowed operators: ==, !=, <, >, <=, >=, +, -, *,\n  /, **, %\n- Use individual named variables: a1, a2, a3...\n  NOT arrays a[1] or sets A\n- Expand all sums explicitly:\n  \"a1 + a2 + a3 == 55\" NOT \"sum([a1,a2,a3])\"\n- NO Python builtins: sum(), len(), max(), min(),\n  list(), set(), range(), int()\n- Each z3_formula must be exactly ONE comparison\n  (==, !=, <, >, <=, >=)\n- For multiple values, write separate constraints\n  for each\n\nOutput ONLY the JSON below, nothing else:\n{\"constraints\": [{\"type\": \"equation\",\n  \"expression\": \"x + y == 14\",\n  \"z3_formula\": \"x + y == 14\",\n  \"source_step\": 1}],\n \"answer\": \"final_answer\",\n \"variables\": [\"x\", \"y\"]}\n\nTrace:\n{trace}\n\\end{lstlisting}\n\n\\paragraph{Logical Constraint Extraction (LOGIC\\_EXTRACTION\\_PROMPT).}\n\nUsed for ProofWriter and FOLIO datasets.\n\n\\begin{lstlisting}\nIMPORTANT: You are an EXTRACTION tool, NOT a problem\nsolver.\n- Do NOT re-solve or re-reason about the problem.\n- Do NOT verify whether the trace's reasoning is\n  correct.\n- ONLY extract the logical constraints that are\n  explicitly stated or used in the trace below.\n- Output ONLY the JSON object, nothing else.\n\nExtract logical constraints from this reasoning trace\nabout a logic problem.\n\nThe problem has facts (base assertions), rules\n(grounded implications), and derived conclusions.\nConvert each into a Z3 boolean formula.\n\nVariable naming:\n- Unary property: property_entity\n  (e.g., kind_anne, red_charlie, round_fiona)\n- Binary relation: relation_subject_object\n  (e.g., eats_bear_squirrel, likes_lion_cat)\n- Use lowercase with underscores only\n\nConstraint types:\n- \"fact\": a given assertion,\n  e.g., kind_anne == True\n- \"rule\": a grounded implication over specific\n  entities, e.g., Implies(kind_anne, nice_anne)\n- \"derived\": an inferred conclusion from facts +\n  rules, e.g., nice_anne == True\n\nZ3 operators:\n- Implies(a, b) for if-then rules\n- And(a, b, ...) for conjunctive conditions\n- Or(a, b, ...) for disjunctive conditions\n- Not(a) for negation\n- == True / == False for boolean assertions\n\nOutput ONLY the JSON below, nothing else:\n{\"constraints\": [{\"type\": \"fact\",\n  \"expression\": \"kind(anne)\",\n  \"z3_formula\": \"kind_anne == True\",\n  \"source_step\": 1}],\n \"answer\": \"True or False or Unknown\",\n \"variables\": [\"kind_anne\"]}\n\nTrace:\n{trace}\n\\end{lstlisting}\n\n\\paragraph{Output Schema.}\n\nBoth prompts produce a JSON object with the following structure:\n\n\\begin{lstlisting}\n{\n  \"constraints\": [\n    {\n      \"type\": \"&lt;equation|inequality|predicate>\n               or &lt;fact|rule|derived>\",\n      \"expression\": \"&lt;human-readable description>\",\n      \"z3_formula\": \"&lt;Z3-compatible expression>\",\n      \"source_step\": &lt;integer>\n    }\n  ],\n  \"answer\": \"&lt;final answer string>\",\n  \"variables\": [\"&lt;var1>\", \"&lt;var2>\", \"...\"]\n}\n\\end{lstlisting}\n\nThe pipeline additionally injects an \\texttt{answer\\_assertion} constraint per trace (not produced by the LLM):\n\n\\begin{lstlisting}\n{\"type\": \"answer_assertion\",\n \"expression\": \"answer is &lt;ans>\",\n \"z3_formula\": \"__sica_answer_&lt;ans> == True\",\n \"source_step\": -1}\n\\end{lstlisting}\n\n\\paragraph{Prompt Selection Logic.}\n\nDomain assignment is determined by dataset: FOLIO and ProofWriter use \\textsc{Logic\\_Extraction\\_Prompt}; GSM8K, AIME, StrategyQA, and ARC-Challenge use \\textsc{Extraction\\_Prompt}. StrategyQA and ARC-Challenge are assigned to the mathematical prompt because their reasoning structure does not involve formal logic predicates or implications, despite StrategyQA producing boolean answers.\n\n\n\\section{Z3 MaxSAT Evaluation Pseudocode}\n\\label{app:z3-pseudocode}\n\nAlgorithm~\\ref{alg:maxsat} describes the Z3 MaxSAT solving procedure. Algorithm~\\ref{alg:scorer} describes the source-trace attribution scoring.\n\nDomain constraint variables (e.g., \\texttt{x + y == 14}) and answer assertion variables (e.g., \\texttt{\\_\\_sica\\_answer\\_42 == True}) are logically independent in the Z3 formulation. Discriminative signal arises solely from conflicts among domain constraints: when traces supporting different answers produce mutually contradictory constraints, the solver excludes the lower-weight subset, and the scorer penalizes the corresponding answers.\n\n\\begin{algorithm}[h]\n\\caption{Z3 Weighted Partial MAX-SAT}\n\\label{alg:maxsat}\n\\begin{algorithmic}[1]\n\\Require Deduplicated constraint set $\\mathcal{C} = \\{(c_m, w_m, S_m)\\}_{m=1}^M$ where $c_m$ is a Z3 formula, $w_m$ is weight, $S_m$ is the set of source trace indices\n\\Ensure Partition $(\\mathcal{C}^*, \\mathcal{C}^{\\setminus})$ where $\\mathcal{C}^*$ is the max-weight satisfiable subset\n\\State $\\textit{opt} \\gets \\textsc{Z3.Optimize()}$\n\\For{$m = 1, \\ldots, M$}\n    \\State $b_m \\gets$ fresh Boolean indicator\n    \\State $\\textit{opt}.\\textsc{Add}(b_m \\Rightarrow c_m)$ \\Comment{soft clause guarded by indicator}\n    \\State $\\textit{opt}.\\textsc{AddSoft}(b_m,\\; \\text{weight}=w_m)$\n\\EndFor\n\\State $\\textit{result} \\gets \\textit{opt}.\\textsc{Check}()$\n\\State $\\textit{model} \\gets \\textit{opt}.\\textsc{Model}()$\n\\State $\\mathcal{C}^* \\gets \\{(c_m, w_m, S_m) : \\textit{model}(b_m) = \\top\\}$\n\\State $\\mathcal{C}^{\\setminus} \\gets \\mathcal{C} \\setminus \\mathcal{C}^*$\n\\State \\Return $(\\mathcal{C}^*, \\mathcal{C}^{\\setminus})$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\begin{algorithm}[h]\n\\caption{Source-Trace Attribution Scoring}\n\\label{alg:scorer}\n\\begin{algorithmic}[1]\n\\Require Satisfied set $\\mathcal{C}^*$, excluded set $\\mathcal{C}^{\\setminus}$, candidate answers $\\mathcal{A}$, trace-answer mapping $\\tau: \\text{trace\\_idx} \\to a$, penalty weight $\\alpha$\n\\Ensure Score $s(a)$ for each $a \\in \\mathcal{A}$\n\\For{each $a \\in \\mathcal{A}$}\n    \\State $T_a \\gets \\{i : \\tau(i) = a\\}$ \\Comment{trace indices producing answer $a$}\n    \\State $\\textit{pos}(a) \\gets \\sum_{(c,w,S) \\in \\mathcal{C}^*} w \\cdot \\mathbf{1}[S \\cap T_a \\neq \\emptyset]$\n    \\State $\\textit{neg}(a) \\gets \\sum_{(c,w,S) \\in \\mathcal{C}^{\\setminus}} w \\cdot \\mathbf{1}[S \\cap T_a \\neq \\emptyset]$\n    \\State $s(a) \\gets \\textit{pos}(a) - \\alpha \\cdot \\textit{neg}(a)$\n\\EndFor\n\\State \\Return $a^* = \\arg\\max_{a \\in \\mathcal{A}} s(a)$\n\\end{algorithmic}\n\\end{algorithm}\n\n\n\\section{Capability-Accuracy Constraint Diagnostics}\n\\label{app:diagnostics}\n\\label{app:cil}\n\n\\paragraph{Conditional Correction Ratio.}\nWe define the \\textit{Conditional Correction Ratio} (CCR) to summarize verifier--generator complementarity:\n\\begin{equation}\n\\label{eq:cil}\n\\text{CCR}(V, G) = \\log \\frac{P(V \\text{ correct} \\mid G \\text{ wrong})}{P(V \\text{ correct} \\mid G \\text{ correct})}.\n\\end{equation}\n$\\text{CCR} > 0$ means $V$ preferentially corrects $G$'s errors; $\\text{CCR} < 0$ indicates shared bias. CCR links our findings: (1)~SCB corresponds to $\\text{CCR}(\\text{self}, G) \\approx 0$; (2)~Finding~2 predicts $\\text{CCR}(V, G) > 0$ when $V$ is independent and capable.\n\n\\paragraph{Empirical CCR across verifier--generator pairs.}\nTable~\\ref{tab:cil_empirical} reports CCR for eight verifier--generator--dataset conditions, sorted by CCR descending. All three cross-architecture NLI pairs on ProofWriter yield $\\text{CCR} > 0$ (verifier preferentially corrects generator errors), while all three same-model SICA conditions yield $\\text{CCR} < 0$ (shared bias). CCR correlates with combo gain: Spearman $\\rho = 0.839$, 95\\% bootstrap CI $[0.338, 0.990]$; LOO-robust (min $p = 0.014$). Four of eight conditions share the DeBERTa verifier, yielding effective $n < 10$; results should be interpreted as a consistent pattern rather than a precise effect size.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Empirical CCR across eight verifier--generator conditions (sorted by CCR descending). $\\text{CCR} > 0$: cross-architecture NLI verifiers on ProofWriter. $\\text{CCR} < 0$: same-model SICA or mismatched capability gap.}\n\\label{tab:cil_empirical}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lllrr@{}}\n\\toprule\nGenerator & Verifier & Dataset & CCR & $\\Delta$ (pp) \\\\\n\\midrule\nMistral-7B & BART-MNLI & PW-600 & $+$1.86 & $+$5.17 \\\\\nMistral-7B & DeBERTa-MNLI & PW-600 & $+$1.67 & $+$6.67 \\\\\nMistral-7B & RoBERTa-MNLI & PW-600 & $+$1.42 & $+$4.17 \\\\\n\\addlinespace\nQwen2.5-14B & DeBERTa-MNLI & PW-600 & $-$0.21 & $+$0.33 \\\\\nMistral-7B & DeBERTa-MNLI & FOLIO-204 & $-$0.47 & $+$2.94 \\\\\n\\addlinespace\nMistral-7B & SICA & FOLIO-204 & $-$2.93 & $+$3.43 \\\\\nQwen2.5-14B & SICA & PW-600 & $-$4.21 & $-$2.50 \\\\\nMistral-7B & SICA & PW-600 & $-$4.61 & $-$2.83 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Per-condition diagnostics.}\nTable~\\ref{tab:capability_trap} reports per-condition diagnostic metrics referenced in \\S\\ref{sec:entropy}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrrrr@{}}\n\\toprule\nModel & Domain & $C_0$ (\\%) & Extr.\\ Rate & Contr.\\ Rate & $\\Delta$ (pp) \\\\\n\\midrule\nQwen2.5-14B & FOLIO & 35.3 & 0.89 & 0.022 & 0.00 \\\\\nQwen2.5-14B & ProofWriter & 39.2 & 0.89 & 0.022 & $+$0.33 \\\\\nQwen2.5-14B & StrategyQA$^\\dagger$ & 10.0 & 0.70 & --- & $+$3.33 \\\\\nQwen2.5-14B & ARC-Chall.$^\\dagger$ & 5.0 & 1.00 & --- & $-$1.67 \\\\\nQwen2.5-7B & FOLIO+PW$^\\dagger$ & 42.1 & 0.94 & 0.027 & 0.00 \\\\\nMistral-7B & FOLIO+PW$^\\dagger$ & 50.0 & 0.88 & 0.056 & 0.00 \\\\\nLLaMA-3.1-8B & StrategyQA & 41.0 & --- & --- & $+$2.00 \\\\\nLLaMA-3.1-8B & FOLIO & 61.8 & 0.94 & 0.062 & $-$4.41 \\\\\nDeepSeek-R1-7B & FOLIO+PW$^\\dagger$ & 58.3 & 0.84 & 0.037 & $-$3.33 \\\\\nQwQ-32B & Combined$^\\dagger$ & 2.6 & --- & --- & 0.00 \\\\\nQwen2.5-14B & GSM8K$^\\dagger$ & 13.3 & 0.15 & --- & 0.00 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Capability-accuracy constraint diagnostics. $C_0$: fraction of questions with multiple distinct candidate answers across $K=12$ traces. Extraction rate: fraction of traces yielding at least one parseable logical constraint. Contradiction rate: fraction of extracted constraint sets with internal contradictions. $\\Delta$: SICA$-$SC gap (pp). $\\dagger$: $n \\leq 60$. Dashes indicate conditions where extraction diagnostics were not computed (StrategyQA uses boolean answers without symbolic extraction; QwQ-32B Combined had near-zero $C_0$, making extraction analysis uninformative). This table includes additional exploratory conditions not reported in Table~\\ref{tab:main_results}.}\n\\label{tab:capability_trap}\n\\end{table}\n\n\n\\section{Statistical Power Analysis}\n\\label{app:power}\n\nWe compute the minimum detectable effect (MDE) for each condition at $\\alpha = 0.05$ and 80\\% power using exact binomial power calculations over McNemar discordant pairs. Table~\\ref{tab:power} reports three grouped conditions with $n \\geq 200$ (Qwen2.5-14B FOLIO and ProofWriter are pooled into a single $n{=}804$ analysis, corresponding to four Table~\\ref{tab:main_results} rows), which constitute our confirmatory analyses. The remaining seven conditions ($n \\leq 60$) yield infinite MDE due to insufficient discordant pairs and serve only as regime characterization.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lrrrrr}\n\\toprule\n\\textbf{Condition} & $n$ & \\textbf{MDE} & \\textbf{Obs.\\ $\\Delta$} & \\textbf{Obs.\\ Pow.} \\\\\n\\midrule\nQwen-14B FOLIO+PW   & 804 & 1.86pp & $+$0.25pp & 5.7\\%  \\\\\nLLaMA-8B StrategyQA  & 200 & 4.64pp & $+$2.00pp & 20.6\\% \\\\\nLLaMA-8B FOLIO       & 204 & 4.84pp & $-$4.41pp & 18.6\\% \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Power analysis for confirmatory conditions ($n \\geq 200$). MDE = minimum detectable effect at 80\\% power. All observed effects fall below their respective MDEs, and observed power remains below 21\\% in every case.}\n\\label{tab:power}\n\\end{table}\n\nThe largest study (Qwen-14B, $n{=}804$, 30 discordant pairs) can detect effects as small as 1.86pp, yet the observed $\\Delta$ of $+$0.25pp is an order of magnitude smaller. The two LLaMA-8B conditions require effects of 4.64pp and 4.84pp to reach significance; neither observed $\\Delta$ approaches these thresholds. All three conditions are consistent with the null hypothesis that SICA provides no accuracy gain over self-consistency.\n\n\n\\section{Bootstrap Confidence Intervals}\n\\label{app:bootstrap}\n\nWe compute 95\\% confidence intervals for $\\Delta(\\text{SICA} - \\text{SC})$ via 10{,}000 bootstrap resamples (percentile method, seed 42). Table~\\ref{tab:bootstrap} reports the results for the three confirmatory conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lrrl}\n\\toprule\n\\textbf{Condition} & $n$ & \\textbf{Obs.\\ $\\Delta$} & \\textbf{95\\% CI} \\\\\n\\midrule\nQwen-14B FOLIO+PW   & 804 & $+$0.25pp & [$-$1.12, $+$1.62] \\\\\nLLaMA-8B StrategyQA  & 200 & $+$2.00pp & [$-$1.50, $+$5.50] \\\\\nLLaMA-8B FOLIO       & 204 & $-$4.41pp & [$-$5.88, $+$0.98] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Bootstrap 95\\% confidence intervals for $\\Delta(\\text{SICA} - \\text{SC})$ in percentage points. All intervals include zero, consistent with no reliable accuracy difference.}\n\\label{tab:bootstrap}\n\\end{table}\n\nAll three intervals contain zero. The narrowest interval (Qwen-14B, [$-$1.12, $+$1.62]) rules out practically meaningful gains ($>$2pp) even in the most favorable case. The widest interval (LLaMA-8B FOLIO, [$-$5.88, $+$0.98]) skews negative, indicating that SICA may slightly hurt accuracy in this condition. These results corroborate the McNemar tests and power analysis: no condition provides evidence that logical constraint aggregation improves over majority voting.\n\n\n\\section{Case Studies: Discordant Predictions}\n\\label{app:case-studies}\n\nAmong 804 problems, SICA and SC agree on 773 (96.1\\%). The 31 discordant cases comprise 16 SICA wins (SICA correct, SC wrong), 14 SC wins (SC correct, SICA wrong), and 1 where both select different wrong answers. All 31 occur at exact ties (entropy${=}1.0$, 6:6 vote split) or near-ties (entropy${\\geq}0.9183$, 8:4 at most), since SICA can differ from SC only when constraint weights shift the majority away from SC's tiebreak choice. We present three representative cases that illustrate the mechanism behind capability-accuracy constraint failures.\n\n\\paragraph{Case 1: SICA Wins (folio\\_134, FOLIO).}\n\n\\emph{Premises}: Some mammals have teeth. Platypus have no teeth. Platypus are mammals. Humans have teeth. \\emph{Conclusion}: Humans are mammals. \\emph{Gold}: Unknown.\n\nThe premises state that \\emph{some} mammals have teeth and that humans have teeth, but ``having teeth'' is not sufficient for ``being a mammal'' under open-world semantics. SC produces a 6:6 split (Unknown:6, True:6) and tiebreaks alphabetically to True (wrong). SICA extracts 7 constraints; MaxSAT excludes 1 constraint inconsistent with the rest, reducing the weighted score for True-voting traces and tipping the aggregation to Unknown (correct). The excluded constraint likely captured an incorrect inference step (e.g., affirming the consequent) present only in True-voting traces. While SICA succeeds here, the success is coincidental: the excluded constraint happens to anti-correlate with the correct answer.\n\n\\paragraph{Case 2: SC Wins (ProofWriter-1066\\_Q6, ProofWriter).}\n\n\\emph{Key chain}: White(Bob)$\\to$Round(Bob) [white things are round] $\\to$ Young(Bob) [all round things are young]. \\emph{Conclusion}: ``Bob is not young.'' \\emph{Gold}: False (Bob IS young).\n\nSC produces a 6:6 split (False:6, True:6) and tiebreaks to False (correct). SICA extracts 17 constraints; MaxSAT excludes 2 that appear preferentially in False-voting traces. These excluded constraints likely captured correct intermediate derivations (e.g., \\texttt{young\\_bob == True}) that appeared only in traces completing the full deduction chain. By excluding them, MaxSAT removes evidence supporting the correct answer. SICA selects True (wrong). This case illustrates how self-extracted constraints can systematically mislead: correct reasoning steps become discriminative signals that the solver mistakenly penalizes.\n\n\\paragraph{Case 3: Non-discriminative Constraints (ProofWriter-903\\_Q6, ProofWriter).}\n\n\\emph{Key chain}: Nice(Mouse)$\\to$Cold(Mouse) [all nice people are cold] $\\to$ Chases(Mouse,Mouse) [nice and cold $\\to$ chase mouse]. \\emph{Conclusion}: ``The mouse does not chase the mouse.'' \\emph{Gold}: False.\n\nSC produces a 6:6 split (False:6, Unknown:6) and tiebreaks to False (correct). SICA extracts 44 constraints but excludes only 1 (2.3\\%). The remaining 43 are domain facts and grounded rules (\\texttt{nice\\_mouse == True}, \\texttt{Implies(nice\\_mouse, cold\\_mouse)}, etc.) that Z3 satisfies identically regardless of the final answer. Both False-voting and Unknown-voting traces share the same premises and grounded rules; they differ only in whether the trace completed the full derivation chain. The single excluded constraint carries negligible weight against 43 shared constraints, so SICA collapses to SC.\n\n\\paragraph{Pattern.}\n\nThese cases exemplify the general pattern across the 773 agreeing problems: the vast majority of extracted constraints encode shared domain structure rather than answer-specific reasoning, and MaxSAT aggregation degenerates to majority vote. Table~\\ref{tab:case_summary} summarizes.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Summary of three representative discordant cases. All occur at exact 6:6 vote ties. Constraint exclusion can break ties in either direction (Cases 1--2) or have no effect (Case 3).}\n\\label{tab:case_summary}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lllcccc@{}}\n\\toprule\nCase & ID & Gold & SC & SICA & \\#Constr. & Excl.\\ (\\%) \\\\\n\\midrule\n1 (SICA win) & folio\\_134 & Unknown & True $\\times$ & Unknown $\\checkmark$ & 7 & 1 (14.3\\%) \\\\\n2 (SC win) & PW-1066\\_Q6 & False & False $\\checkmark$ & True $\\times$ & 17 & 2 (11.8\\%) \\\\\n3 (Non-disc.) & PW-903\\_Q6 & False & False $\\checkmark$ & False $\\checkmark$ & 44 & 1 (2.3\\%) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Oracle Control}\n\\label{app:oracle}\n\\label{sec:oracle}\n\\label{app:pw-oracle-subtype}\n\nReplacing self-extracted constraints with gold annotations (FOLIO logical formulae, ProofWriter DSL), Oracle-SICA yields $+29.90$\\,pp on Mistral-7B FOLIO ($p < 10^{-13}$), $+13.73$\\,pp on Qwen2.5-14B FOLIO ($p = 2.0 \\times 10^{-7}$), and $+17.17$\\,pp on ProofWriter ($p < 10^{-14}$). Z3 agrees with gold labels on 95.1\\% (FOLIO) and 97.1\\% (ProofWriter). The MAX-SAT mechanism is sound; Mistral-7B's best self-extracted $\\Delta$ ($+3.43$\\,pp) captures only 11.5\\% of its oracle ceiling. For Qwen2.5-14B on ProofWriter, the gap is wider still: self-extraction degrades accuracy ($-2.50$\\,pp) against an oracle ceiling of $+17.17$\\,pp, indicating that stronger models do not self-extract more effectively.\n\n\\paragraph{ProofWriter per-subtype analysis.} ProofWriter problems encode deductive rules as Domain-Specific Language (DSL) logic programs. Each problem uses one of four predicate subtypes: attribute predicates with or without negation (AttNeg, AttNoneg), and relation predicates with or without negation (RelNeg, RelNoneg). Relation predicates involve binary relations between entities (e.g., \\texttt{eats(bear, squirrel)}), while attribute predicates assign unary properties (e.g., \\texttt{kind(anne)}).\n\nThe oracle pipeline parses these DSL annotations deterministically into Z3 formulas without any LLM involvement. Of the 600 ProofWriter problems, 594 (99.0\\%) produce valid Z3 parses; the remaining 6 fail due to unsupported DSL constructs. Across all 7{,}128 trace-problem pairs submitted to Z3, the solver returns a result in every case (0\\% solver errors). Z3 evaluations agree with ground-truth labels on 577 of 594 parseable problems (97.14\\%), confirming that the deterministic DSL-to-Z3 translation faithfully preserves problem semantics.\n\nTable~\\ref{tab:pw_oracle_subtype} reports the per-subtype breakdown. Relation-predicate subtypes show substantially larger gains than attribute-predicate subtypes: RelNeg improves by $+28.58$~pp and RelNoneg by $+23.29$~pp, compared to $+10.00$~pp for AttNeg and $+8.44$~pp for AttNoneg. Relation predicates involve longer reasoning chains with more intermediate entities, producing greater answer diversity across traces ($C_0$) and more opportunities for oracle constraints to correct errors.\n\n\\begin{table}[h]\n\\centering\n\\caption{ProofWriter oracle experiment per-subtype breakdown. Oracle-SICA uses gold DSL annotations parsed deterministically to Z3 for consistency checking. Relation-predicate subtypes (RelNeg, RelNoneg) show larger gains than attribute-predicate subtypes; relation subtypes involve longer reasoning chains and benefit more from oracle constraints. Bold indicates best accuracy per row.}\n\\label{tab:pw_oracle_subtype}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nSubtype & $n$ & SC Acc (\\%) & Oracle Acc (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\nAttNoneg & 154 & 90.26 & \\textbf{98.70} & +8.44 \\\\\nAttNeg & 160 & 81.88 & \\textbf{91.88} & +10.00 \\\\\nRelNoneg & 146 & 60.96 & \\textbf{84.25} & +23.29 \\\\\nRelNeg & 140 & 60.71 & \\textbf{89.29} & +28.58 \\\\\n\\midrule\nOverall & 600 & 74.00 & \\textbf{91.17} & +17.17 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Constraint Ablation Details}\n\\label{app:ablation}\n\\label{sec:ablation}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Constraint ablation (Qwen2.5-14B, $n = 804$). Agreement: predictions identical to SC. MAX-SAT and count-only produce nearly identical predictions, confirming that self-extracted constraints carry no signal beyond vote counts.}\n\\label{tab:ablation}\n\\begin{tabular}{@{}lrc@{}}\n\\toprule\nAggregation & Acc.\\ (\\%) & Agreement w/ SC \\\\\n\\midrule\nSC (majority vote) & 76.24 & --- \\\\\nSICA (MAX-SAT) & 76.49 & 773\\,/\\,804 \\\\\nCount-only & 76.62 & 774\\,/\\,804 \\\\\nRandom-weight & 75.87 & 764\\,/\\,804 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MAX-SAT vs.\\ count-only agreement across constraint weight $\\alpha \\in [0,1]$ on FOLIO ($n = 204$). Mistral-7B (BR $= 4.97\\times$, seed 42); Qwen2.5-14B (BR $= 3.85\\times$, seed 123). $\\alpha{=}0$: pure Z3 satisfiability (no source-attribution); $\\alpha{=}1$: full source-attribution penalty. Agreement $\\geq 99\\%$ at all $\\alpha$ including endpoints, confirming vacuity is weight-insensitive.}\n\\label{tab:alpha-ablation}\n\\begin{tabular}{@{}crr@{}}\n\\toprule\n$\\alpha$ & Mistral Agr.\\ (\\%) & Qwen2.5 Agr.\\ (\\%) \\\\\n\\midrule\n0.0 & 100 & 100 \\\\\n0.1 & 100 & 100 \\\\\n0.3 & 100 & 100 \\\\\n0.5 & 100 & 100 \\\\\n0.7 & 99 & 100 \\\\\n0.9 & 99 & 100 \\\\\n1.0 & 99 & 100 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Remediation Strategy Details}\n\\label{app:remediation}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Nine prompt-level remediation strategies. Baseline: Qwen2.5-14B FOLIO, SC $= 75.98\\%$, $\\Delta = -0.49$\\,pp. None reaches significance. Three method-level strategies are reported in Table~\\ref{tab:method_interventions}.}\n\\label{tab:remediation}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrl@{}}\n\\toprule\nStrategy & Target & $\\Delta$ (pp) & Key finding \\\\\n\\midrule\nContrastive$^a$ & Prompt & $-$1.10 & non-disc.\\ 6.0\\% ($\\downarrow$ from 8.2\\%) \\\\\nCross-model$^b$ & Architecture & 0.00 & disc.\\ 0\\% (weak$\\to$strong); $\\pm$1\\,pp (strong$\\to$weak) \\\\\nQwen3-14B$^c$ & Capability & $-$0.49 & $p = 0.655$ \\\\\nZ3 feedback & Solver & --- & 0.9\\% UNSAT trigger \\\\\nCons.\\ filtering & Noise & 0.00 & $T{\\geq}4 \\to$ SC \\\\\nCross-trace UNSAT & Independence & --- & 56.4\\% $\\emptyset$ vars \\\\\n$T{=}1.0$$^d$ & Diversity & 0.00 & isolated peak at $T{=}0.7$ only \\\\\nMulti-temp$^e$ & Diversity & 0.00 & $b{=}5$, $c{=}5$ (balanced) \\\\\nDisc.\\ filtering$^f$ & Filtering & 0.00 & 803/804 agree w/ SICA \\\\\n\\bottomrule\n\\end{tabular}}\\\\[2pt]\n{\\footnotesize $^a$\\,$n{=}182$ (extraction failures excluded). $^b$\\,Weak$\\to$strong: Mistral-7B extracts from Qwen2.5-14B traces. Strong$\\to$weak: Qwen3-14B (60.29\\%) and Qwen2.5-14B (58.33\\%) extract from Mistral-7B FOLIO traces ($n{=}204$); self-extraction baseline 59.31\\%. $^c$\\,$n{=}204$, SC $= 83.33\\%$. $^d$\\,Mistral-7B FOLIO, $n{=}204$. $^e$\\,Mistral-7B FOLIO, $T \\in \\{0.3, 0.7, 1.2\\}$, 4 traces each, $n{=}204$. $^f$\\,Qwen2.5-14B, $n{=}804$; removing non-discriminative constraints.}\n\\end{table}\n\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Method-level interventions on Mistral-7B with McNemar's paired test. All produce neutral-to-catastrophic results. ICG shows two FOLIO seeds; $p$ for the first. {*}{*}{*}\\,$p < 0.001$; {*}{*}\\,$p < 0.01$.}\n\\label{tab:method_interventions}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ll rc rc@{}}\n\\toprule\n& & \\multicolumn{2}{c}{FOLIO ($n = 204$)} & \\multicolumn{2}{c}{LogiQA ($n = 200$)} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){5-6}\nMethod & Target & $\\Delta$ (pp) & $p$ & $\\Delta$ (pp) & $p$ \\\\\n\\midrule\nSC baseline & --- & 0.00 & --- & 0.00 & --- \\\\\nICG & Trace coupling & $-$1.96\\,/\\,$+$1.47 & .206 & $-$0.50 & .706 \\\\\nContrastive & Scoring bias & $\\mathbf{-9.31}$ & .007 & $-$4.50 & .160 \\\\\nDebate & Role diversity & $\\mathbf{-18.63}$ & ${<}.001$ & $\\mathbf{-23.00}$ & ${<}.001$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{Additional Intervention Results}\n\\label{app:additional-interventions}\n\n\\begin{table*}[h]\n\\centering\n\\small\n\\caption{Additional intervention results beyond the nine prompt-level and three method-level strategies reported in the main text. All produce neutral-to-negative results, completing the exhaustive remediation analysis across 27 distinct approaches.}\n\\label{tab:additional_interventions}\n\\begin{tabular}{@{}llllrl@{}}\n\\toprule\n\\# & Method & Type & Target & $\\Delta$ (pp) & Key Finding \\\\\n\\midrule\n13 & PROVE (code verif.) & Paradigm & Formal proof & $-$1.9 & 15.2\\% compilable; conclusive acc.\\ = 50\\% \\\\\n14 & CEGIS (iterative) & Multi-round & Consistency & 0.0$^\\dagger$ & R1 $+$3.43\\,pp then oscillates \\\\\n15 & DeepConf (logprob) & Filtering & Confidence & 0.0 & $\\Delta_{\\text{logprob}} = 0.006$ (no separation) \\\\\n16 & Cross-model SICA & Cross-model & Independence & $-$0.49 & $\\kappa_{\\text{cross}}{=}0.42$ vs $\\kappa_{\\text{within}}{=}0.53$ \\\\\n17 & Problem perturbation & Input diversity & Trace diversity & $<$0 & $\\kappa$ \\emph{increased} to 0.70 (anti-effect) \\\\\n18 & MIN-UNSAT & Solver objective & Constraint sel.\\ & $-$6.5 & Mean excluded constraints $= 1.3$ \\\\\n19 & $\\kappa$-aware SC & Voting rule & Weighted voting & 0.0 & 11/11 conditions $\\Delta = 0$ \\\\\n20 & Z3 trace filter & Trace filtering & Quality & $-$0.49 & Precision 49.1\\%, 7 questions affected \\\\\n21 & Bootstrapped gold & Iterative & Self-improvement & 0.0$^\\dagger$ & R1 $+$2.45\\,pp then oscillates \\\\\n22 & Selective abstention & Diagnostic & Confidence & $+$4.4$^*$ & AUROC $= 0.673$, at 80\\% coverage \\\\\n23 & ASCII perturbation & Input diversity & Format diversity & 0.0 & $\\kappa$: $0.39 \\to 0.36$ (negligible) \\\\\n\\addlinespace",
      "numLines": 500,
      "startLine": 1,
      "totalLines": 1544
    }
  },
  "sourceToolAssistantUUID": "560cfe60-01dc-4f3f-8157-ac33fff6a79d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 46 · 2026-05-24T04:28:48.872Z_

<details open><summary>🔧 Tool call — Read · `toolu_01YTV5C5qtgng7Q3AifX9r4D`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures/gen_f6_kappa_accuracy_scatter.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5d57b38d-6693-429b-8bf9-abc481de24de",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "3552cfa3-1a66-4e0c-983f-c37f8fc58b9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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

_source line 47 · 2026-05-24T04:28:48.877Z_

<details><summary>↩ Tool result · `toolu_01YTV5C5qtgng7Q3AifX9r4D`</summary>

```text
1	import matplotlib
2	matplotlib.use('Agg')
3	import matplotlib.pyplot as plt
4	import matplotlib.lines as mlines
5	import numpy as np
6	
7	plt.rcParams.update({
8	    'font.family': 'DejaVu Sans',
9	    'font.size': 11,
10	    'axes.titlesize': 13,
11	    'axes.labelsize': 12,
12	    'xtick.labelsize': 10,
13	    'ytick.labelsize': 10,
14	    'legend.fontsize': 8.5,
15	    'figure.dpi': 300,
16	    'savefig.dpi': 300,
17	    'savefig.bbox': 'tight',
18	    'savefig.pad_inches': 0.05,
19	    'axes.spines.top': False,
20	    'axes.spines.right': False,
21	})
22	
23	# --- Mistral-7B method points (filled markers) ---
24	m_labels = ['Debate', 'Diverse-Prompt', 'SC (Mistral)', 'ICG']
25	m_kappa  = [0.155,    0.403,            0.438,          0.465]
26	m_acc    = [38.24,    54.41,            56.86,          51.96]
27	m_colors = ['#D55E00', '#009E73', '#0072B2', '#E69F00']
28	m_markers = ['v',      'D',       's',       'o']
29	
30	# --- Cross-model SC points (open markers) ---
31	x_labels = ['LLaMA-8B', 'Qwen-7B', 'Qwen-14B']
32	x_kappa  = [0.412,      0.658,     0.738]
33	x_acc    = [66.18,      75.98,     75.98]
34	x_color  = '#882D8B'
35	x_markers = ['^',       'p',       'h']
36	
37	fig, ax = plt.subplots(figsize=(5.2, 3.8))
38	
39	# Same-model ceiling shaded region
40	ax.axvspan(0.40, 0.47, color='#888888', alpha=0.08, zorder=0)
41	ax.text(0.435, 82, 'same-model\nceiling', ha='center', va='top',
42	        fontsize=7.5, color='#888888', fontstyle='italic', linespacing=1.1)
43	
44	# SC baseline horizontal line (Mistral)
45	ax.axhline(y=56.86, color='#AAAAAA', linestyle='--', linewidth=0.8, zorder=1)
46	ax.text(0.08, 57.8, 'SC baseline (Mistral)', ha='left', va='bottom',
47	        fontsize=7.5, color='#999999')
48	
49	# Mistral-7B method points (filled)
50	for i in range(len(m_labels)):
51	    ax.scatter(m_kappa[i], m_acc[i], c=m_colors[i], marker=m_markers[i],
52	               s=110, zorder=5, edgecolors='white', linewidths=0.5)
53	
54	# Cross-model SC points (open)
55	for i in range(len(x_labels)):
56	    ax.scatter(x_kappa[i], x_acc[i], facecolors='white', edgecolors=x_color,
57	               marker=x_markers[i], s=120, zorder=5, linewidths=1.8)
58	
59	# --- Annotations ---
60	m_annot = {
61	    'Debate':         {'xy': (10, -2),  'ha': 'left',  'va': 'center'},
62	    'Diverse-Prompt': {'xy': (-8, -12), 'ha': 'right', 'va': 'top'},
63	    'SC (Mistral)':   {'xy': (-8, 6),   'ha': 'right', 'va': 'bottom'},
64	    'ICG':            {'xy': (8, -10),  'ha': 'left',  'va': 'top'},
65	}
66	for i, m in enumerate(m_labels):
67	    cfg = m_annot[m]
68	    ax.annotate(m, (m_kappa[i], m_acc[i]),
69	                xytext=cfg['xy'], textcoords='offset points',
70	                fontsize=8.5, fontweight='bold', color=m_colors[i],
71	                ha=cfg['ha'], va=cfg['va'])
72	
73	x_annot = {
74	    'LLaMA-8B':  {'xy': (8, 4),   'ha': 'left',  'va': 'bottom'},
75	    'Qwen-7B':   {'xy': (-8, 6),  'ha': 'right', 'va': 'bottom'},
76	    'Qwen-14B':  {'xy': (-8, -8), 'ha': 'right', 'va': 'top'},
77	}
78	for i, m in enumerate(x_labels):
79	    cfg = x_annot[m]
80	    ax.annotate(m, (x_kappa[i], x_acc[i]),
81	                xytext=cfg['xy'], textcoords='offset points',
82	                fontsize=8.5, fontweight='bold', color=x_color,
83	                ha=cfg['ha'], va=cfg['va'])
84	
85	# --- Legend ---
86	method_handle = mlines.Line2D([], [], color='#555555', marker='s', markersize=7,
87	                               markerfacecolor='#555555', markeredgecolor='white',
88	                               linestyle='None', label='Mistral-7B methods')
89	cross_handle = mlines.Line2D([], [], color=x_color, marker='^', markersize=7,
90	                              markerfacecolor='white', markeredgecolor=x_color,
91	                              markeredgewidth=1.5, linestyle='None',
92	                              label='Cross-model SC')
93	ax.legend(handles=[method_handle, cross_handle], loc='upper left',
94	          framealpha=0.9, edgecolor='#CCCCCC', borderpad=0.4, handletextpad=0.3)
95	
96	ax.set_xlabel(r"Output Correlation (Fleiss' $\kappa$)")
97	ax.set_ylabel('Accuracy (%)')
98	ax.set_xlim(0.05, 0.82)
99	ax.set_ylim(30, 84)
100	
101	ax.set_xticks([0.1, 0.2, 0.3, 0.4, 0.5, 0.6, 0.7, 0.8])
102	ax.set_yticks([30, 40, 50, 60, 70, 80])
103	
104	fig.text(0.5, -0.02,
105	         r"Note: ICG $\kappa$ measured on per-constraint-set MAX-SAT answers; others use direct trace answers.",
106	         ha='center', va='top', fontsize=7, color='#666666', fontstyle='italic')
107	
108	out_dir = '/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures'
109	fig.savefig(f'{out_dir}/f6_kappa_accuracy_scatter.pdf')
110	fig.savefig(f'{out_dir}/f6_kappa_accuracy_scatter.png')
111	print('Saved PDF and PNG.')
112	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3552cfa3-1a66-4e0c-983f-c37f8fc58b9f",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "688ec291-69e9-49dd-ac71-15fa82f27edb",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures/gen_f6_kappa_accuracy_scatter.py",
      "content": "import matplotlib\nmatplotlib.use('Agg')\nimport matplotlib.pyplot as plt\nimport matplotlib.lines as mlines\nimport numpy as np\n\nplt.rcParams.update({\n    'font.family': 'DejaVu Sans',\n    'font.size': 11,\n    'axes.titlesize': 13,\n    'axes.labelsize': 12,\n    'xtick.labelsize': 10,\n    'ytick.labelsize': 10,\n    'legend.fontsize': 8.5,\n    'figure.dpi': 300,\n    'savefig.dpi': 300,\n    'savefig.bbox': 'tight',\n    'savefig.pad_inches': 0.05,\n    'axes.spines.top': False,\n    'axes.spines.right': False,\n})\n\n# --- Mistral-7B method points (filled markers) ---\nm_labels = ['Debate', 'Diverse-Prompt', 'SC (Mistral)', 'ICG']\nm_kappa  = [0.155,    0.403,            0.438,          0.465]\nm_acc    = [38.24,    54.41,            56.86,          51.96]\nm_colors = ['#D55E00', '#009E73', '#0072B2', '#E69F00']\nm_markers = ['v',      'D',       's',       'o']\n\n# --- Cross-model SC points (open markers) ---\nx_labels = ['LLaMA-8B', 'Qwen-7B', 'Qwen-14B']\nx_kappa  = [0.412,      0.658,     0.738]\nx_acc    = [66.18,      75.98,     75.98]\nx_color  = '#882D8B'\nx_markers = ['^',       'p',       'h']\n\nfig, ax = plt.subplots(figsize=(5.2, 3.8))\n\n# Same-model ceiling shaded region\nax.axvspan(0.40, 0.47, color='#888888', alpha=0.08, zorder=0)\nax.text(0.435, 82, 'same-model\\nceiling', ha='center', va='top',\n        fontsize=7.5, color='#888888', fontstyle='italic', linespacing=1.1)\n\n# SC baseline horizontal line (Mistral)\nax.axhline(y=56.86, color='#AAAAAA', linestyle='--', linewidth=0.8, zorder=1)\nax.text(0.08, 57.8, 'SC baseline (Mistral)', ha='left', va='bottom',\n        fontsize=7.5, color='#999999')\n\n# Mistral-7B method points (filled)\nfor i in range(len(m_labels)):\n    ax.scatter(m_kappa[i], m_acc[i], c=m_colors[i], marker=m_markers[i],\n               s=110, zorder=5, edgecolors='white', linewidths=0.5)\n\n# Cross-model SC points (open)\nfor i in range(len(x_labels)):\n    ax.scatter(x_kappa[i], x_acc[i], facecolors='white', edgecolors=x_color,\n               marker=x_markers[i], s=120, zorder=5, linewidths=1.8)\n\n# --- Annotations ---\nm_annot = {\n    'Debate':         {'xy': (10, -2),  'ha': 'left',  'va': 'center'},\n    'Diverse-Prompt': {'xy': (-8, -12), 'ha': 'right', 'va': 'top'},\n    'SC (Mistral)':   {'xy': (-8, 6),   'ha': 'right', 'va': 'bottom'},\n    'ICG':            {'xy': (8, -10),  'ha': 'left',  'va': 'top'},\n}\nfor i, m in enumerate(m_labels):\n    cfg = m_annot[m]\n    ax.annotate(m, (m_kappa[i], m_acc[i]),\n                xytext=cfg['xy'], textcoords='offset points',\n                fontsize=8.5, fontweight='bold', color=m_colors[i],\n                ha=cfg['ha'], va=cfg['va'])\n\nx_annot = {\n    'LLaMA-8B':  {'xy': (8, 4),   'ha': 'left',  'va': 'bottom'},\n    'Qwen-7B':   {'xy': (-8, 6),  'ha': 'right', 'va': 'bottom'},\n    'Qwen-14B':  {'xy': (-8, -8), 'ha': 'right', 'va': 'top'},\n}\nfor i, m in enumerate(x_labels):\n    cfg = x_annot[m]\n    ax.annotate(m, (x_kappa[i], x_acc[i]),\n                xytext=cfg['xy'], textcoords='offset points',\n                fontsize=8.5, fontweight='bold', color=x_color,\n                ha=cfg['ha'], va=cfg['va'])\n\n# --- Legend ---\nmethod_handle = mlines.Line2D([], [], color='#555555', marker='s', markersize=7,\n                               markerfacecolor='#555555', markeredgecolor='white',\n                               linestyle='None', label='Mistral-7B methods')\ncross_handle = mlines.Line2D([], [], color=x_color, marker='^', markersize=7,\n                              markerfacecolor='white', markeredgecolor=x_color,\n                              markeredgewidth=1.5, linestyle='None',\n                              label='Cross-model SC')\nax.legend(handles=[method_handle, cross_handle], loc='upper left',\n          framealpha=0.9, edgecolor='#CCCCCC', borderpad=0.4, handletextpad=0.3)\n\nax.set_xlabel(r\"Output Correlation (Fleiss' $\\kappa$)\")\nax.set_ylabel('Accuracy (%)')\nax.set_xlim(0.05, 0.82)\nax.set_ylim(30, 84)\n\nax.set_xticks([0.1, 0.2, 0.3, 0.4, 0.5, 0.6, 0.7, 0.8])\nax.set_yticks([30, 40, 50, 60, 70, 80])\n\nfig.text(0.5, -0.02,\n         r\"Note: ICG $\\kappa$ measured on per-constraint-set MAX-SAT answers; others use direct trace answers.\",\n         ha='center', va='top', fontsize=7, color='#666666', fontstyle='italic')\n\nout_dir = '/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures'\nfig.savefig(f'{out_dir}/f6_kappa_accuracy_scatter.pdf')\nfig.savefig(f'{out_dir}/f6_kappa_accuracy_scatter.png')\nprint('Saved PDF and PNG.')\n",
      "numLines": 112,
      "startLine": 1,
      "totalLines": 112
    }
  },
  "sourceToolAssistantUUID": "3552cfa3-1a66-4e0c-983f-c37f8fc58b9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 48 · 2026-05-24T04:28:49.789Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WTMpPmejJh4HbJXCqWCtJs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures/gen_capability_gap_scatter.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "688ec291-69e9-49dd-ac71-15fa82f27edb",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "e2f630e2-d355-453f-9087-bad6b97591cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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

_source line 49 · 2026-05-24T04:28:49.794Z_

<details><summary>↩ Tool result · `toolu_01WTMpPmejJh4HbJXCqWCtJs`</summary>

```text
1	"""Generate capability gap scatter plot for §6.
2	
3	DeBERTa-MNLI primary (6 pts) + LLaMA-8B (1 pt, distinct marker) + multi-verifier (2 pts)
4	+ fine-tuned DeBERTa (2 pts). All gains at w=3.
5	"""
6	import matplotlib
7	matplotlib.use('Agg')
8	import matplotlib.pyplot as plt
9	import numpy as np
10	from scipy.optimize import curve_fit
11	from scipy.stats import spearmanr, linregress
12	
13	plt.rcParams.update({
14	    'font.family': 'serif',
15	    'font.serif': ['Times New Roman', 'DejaVu Serif'],
16	    'font.size': 9,
17	    'axes.labelsize': 10,
18	    'axes.titlesize': 10,
19	    'xtick.labelsize': 8,
20	    'ytick.labelsize': 8,
21	    'legend.fontsize': 7,
22	    'figure.dpi': 300,
23	    'savefig.dpi': 300,
24	    'savefig.bbox': 'tight',
25	    'savefig.pad_inches': 0.08,
26	})
27	
28	# Primary: DeBERTa-MNLI across model x dataset at w=3
29	deberta_pts = [
30	    (-36.76, 0.49, 'Qwen3-14B$_{\\mathrm{think}}$\n(FOLIO)'),
31	    (-33.82, 0.49, 'Qwen3-14B\n(FOLIO)'),
32	    (-30.83, 0.50, 'Qwen3-14B\n(PW-D5)'),
33	    (-19.00, 0.67, 'Qwen2.5-14B\n(PW-D5)'),
34	    (-6.37,  2.94, 'Mistral-7B\n(FOLIO)'),
35	    (15.67,  6.67, 'Mistral-7B\n(ProofWriter)'),
36	]
37	
38	# LLaMA point (different model family, separate marker)
39	llama_pt = (-17.50, 0.83, 'LLaMA-8B\n(PW-D5)')
40	
41	# Secondary: other NLI verifiers on Mistral-7B ProofWriter at w=3
42	multi_nli = [
43	    (-1.66, 4.17, 'RoBERTa'),   # 37.67 - 39.33
44	    (6.84,  5.17, 'BART'),       # 46.17 - 39.33
45	]
46	
47	# Fine-tuned DeBERTa on ProofWriter OWA (99.67% standalone), w=3
48	finetuned_pts = [
49	    (27.17, 11.67, 'LLaMA-8B'),    # 99.67 - 72.50 (finetuned SC)
50	    (60.34, 12.67, 'Mistral-7B'),   # 99.67 - 39.33
51	]
52	
53	dx = np.array([p[0] for p in deberta_pts])
54	dy = np.array([p[1] for p in deberta_pts])
55	
56	# DeBERTa-only (excl. LLaMA) stats
57	rho_excl, p_excl = spearmanr(dx, dy)
58	print(f"DeBERTa-only (excl LLaMA) Spearman rho={rho_excl:.3f} (n={len(dx)}, p={p_excl:.4f})")
59	
60	# All DeBERTa-verifier points (incl. LLaMA)
61	dx_all = np.append(dx, llama_pt[0])
62	dy_all = np.append(dy, llama_pt[1])
63	rho, p_rho = spearmanr(dx_all, dy_all)
64	print(f"DeBERTa-all (incl LLaMA) Spearman rho={rho:.3f} (n={len(dx_all)}, p={p_rho:.4f})")
65	slope, intercept, r_value, p_lin, _ = linregress(dx_all, dy_all)
66	print(f"DeBERTa-all linear: R²={r_value**2:.3f}, p={p_lin:.4f}")
67	
68	# Sigmoid with Director's parameters as guide
69	def sigmoid(x, L, k, x0, b):
70	    return L / (1 + np.exp(-k * (x - x0))) + b
71	
72	# Use all points for visual fit (DeBERTa + LLaMA + multi-NLI)
73	all_pts = deberta_pts + [llama_pt] + multi_nli
74	ax_all = np.array([p[0] for p in all_pts])
75	ay_all = np.array([p[1] for p in all_pts])
76	
77	try:
78	    popt, _ = curve_fit(sigmoid, ax_all, ay_all,
79	                        p0=[3.5, 0.3, 1.0, 0.2],
80	                        bounds=([0.5, 0.01, -10, -1], [5.0, 2.0, 15, 2.0]),
81	                        maxfev=50000)
82	    x_fit = np.linspace(-42, 68, 500)
83	    y_sig = sigmoid(x_fit, *popt)
84	    ss_res = np.sum((ay_all - sigmoid(ax_all, *popt))**2)
85	    ss_tot = np.sum((ay_all - np.mean(ay_all))**2)
86	    r2_sig = 1 - ss_res / ss_tot
87	    inflection = popt[2]
88	    print(f"Sigmoid ({len(ax_all)}pt): R²={r2_sig:.3f}, inflection={inflection:.1f}pp, L={popt[0]:.2f}, k={popt[1]:.3f}")
89	    has_sigmoid = True
90	except Exception as e:
91	    print(f"Sigmoid fit failed: {e}")
92	    has_sigmoid = False
93	    x_fit = np.linspace(-42, 68, 500)
94	
95	# Plot
96	fig, ax = plt.subplots(figsize=(3.8, 2.8))
97	fig.subplots_adjust(left=0.16, bottom=0.20, right=0.96, top=0.94)
98	
99	# DeBERTa primary points (Mistral/Qwen generators)
100	ax.scatter(dx, dy, marker='o', c='#2166ac', s=50, zorder=5,
101	           label='DeBERTa-MNLI', edgecolors='white', linewidths=0.5)
102	
103	# LLaMA generator (different model family)
104	ax.scatter([llama_pt[0]], [llama_pt[1]], marker='D', c='#e66101', s=50, zorder=5,
105	           label='DeBERTa-MNLI (LLaMA)', edgecolors='white', linewidths=0.5)
106	
107	# Multi-NLI secondary points
108	mx = [p[0] for p in multi_nli]
109	my = [p[1] for p in multi_nli]
110	ml = [p[2] for p in multi_nli]
111	ax.scatter([mx[0]], [my[0]], marker='s', c='#b2182b', s=40, zorder=5,
112	           label='RoBERTa-MNLI', edgecolors='white', linewidths=0.5)
113	ax.scatter([mx[1]], [my[1]], marker='^', c='#4dac26', s=40, zorder=5,
114	           label='BART-MNLI', edgecolors='white', linewidths=0.5)
115	
116	# Fine-tuned DeBERTa points
117	fx = [p[0] for p in finetuned_pts]
118	fy = [p[1] for p in finetuned_pts]
119	ax.scatter(fx, fy, marker='*', c='#7b3294', s=100, zorder=6,
120	           label='Fine-tuned DeBERTa', edgecolors='white', linewidths=0.5)
121	
122	# Sigmoid curve
123	if has_sigmoid:
124	    ax.plot(x_fit, y_sig, '-', color='#555555', linewidth=1.0, alpha=0.6,
125	            label=f'Sigmoid fit')
126	
127	# Annotations for DeBERTa points
128	annot_config = [
129	    (-36.76, 0.49, 'Qwen3-14B$_{\\mathrm{think}}$\nFOLIO', (6, -3), 'left'),
130	    (-35.29, 0.49, 'Qwen3-14B\nFOLIO', (6, -15), 'left'),
131	    (-30.83, 0.50, 'Qwen3-14B\nPW-D5', (6, 3), 'left'),
132	    (-19.00, 0.67, 'Qwen2.5-14B\nPW-D5', (6, -8), 'left'),
133	    (-6.37,  2.94, 'Mistral-7B\nFOLIO', (6, -8), 'left'),
134	    (15.67,  6.67, 'Mistral-7B\nPW-D5', (-6, 5), 'right'),
135	]
136	for x, y, lbl, offset, ha in annot_config:
137	    ax.annotate(lbl, (x, y), textcoords='offset points',
138	                xytext=offset, fontsize=5.5, ha=ha, color='#444444',
139	                linespacing=0.9)
140	
141	# LLaMA annotation (distinct color)
142	ax.annotate('LLaMA-8B\nPW-D5', (llama_pt[0], llama_pt[1]),
143	            textcoords='offset points', xytext=(6, -10), fontsize=5.5,
144	            ha='left', color='#e66101', linespacing=0.9)
145	
146	# Annotations for multi-NLI
147	ax.annotate('RoBERTa', (mx[0], my[0]), textcoords='offset points',
148	            xytext=(5, 5), fontsize=5.5, ha='left', color='#b2182b')
149	ax.annotate('BART', (mx[1], my[1]), textcoords='offset points',
150	            xytext=(5, 5), fontsize=5.5, ha='left', color='#4dac26')
151	
152	# Annotations for fine-tuned
153	ax.annotate('LLaMA-8B\n(fine-tuned)', (fx[0], fy[0]), textcoords='offset points',
154	            xytext=(-6, 5), fontsize=5.5, ha='right', color='#7b3294', linespacing=0.9)
155	ax.annotate('Mistral-7B\n(fine-tuned)', (fx[1], fy[1]), textcoords='offset points',
156	            xytext=(-6, 5), fontsize=5.5, ha='right', color='#7b3294', linespacing=0.9)
157	
158	# Reference lines
159	ax.axhline(0, color='black', linewidth=0.3, alpha=0.2)
160	ax.axvline(0, color='black', linewidth=0.5, alpha=0.25, linestyle=':')
161	
162	# Region labels
163	ax.text(-21, 14.0, 'verifier $<$ generator', fontsize=6.5, color='#aaaaaa',
164	        ha='center', style='italic')
165	ax.text(40, 14.0, 'verifier $>$ generator', fontsize=6.5, color='#aaaaaa',
166	        ha='center', style='italic')
167	
168	ax.set_xlabel('Capability gap (verifier $-$ generator SC, pp)')
169	ax.set_ylabel('Combo gain over SC (pp, $w{=}3$)')
170	ax.set_xlim(-42, 68)
171	ax.set_ylim(-0.3, 15.0)
172	ax.legend(loc='lower right', framealpha=0.9, edgecolor='#cccccc',
173	          borderpad=0.3, handletextpad=0.4, bbox_to_anchor=(1.0, 0.0))
174	ax.spines['top'].set_visible(False)
175	ax.spines['right'].set_visible(False)
176	
177	# no tight_layout — manual subplots_adjust above
178	outdir = '/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures'
179	fig.savefig(f'{outdir}/capability_gap_scatter.pdf')
180	fig.savefig(f'{outdir}/capability_gap_scatter.png')
181	print("Saved to", outdir)
182	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e2f630e2-d355-453f-9087-bad6b97591cc",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "dece1e11-0585-4270-b037-ac831c13c693",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures/gen_capability_gap_scatter.py",
      "content": "\"\"\"Generate capability gap scatter plot for §6.\n\nDeBERTa-MNLI primary (6 pts) + LLaMA-8B (1 pt, distinct marker) + multi-verifier (2 pts)\n+ fine-tuned DeBERTa (2 pts). All gains at w=3.\n\"\"\"\nimport matplotlib\nmatplotlib.use('Agg')\nimport matplotlib.pyplot as plt\nimport numpy as np\nfrom scipy.optimize import curve_fit\nfrom scipy.stats import spearmanr, linregress\n\nplt.rcParams.update({\n    'font.family': 'serif',\n    'font.serif': ['Times New Roman', 'DejaVu Serif'],\n    'font.size': 9,\n    'axes.labelsize': 10,\n    'axes.titlesize': 10,\n    'xtick.labelsize': 8,\n    'ytick.labelsize': 8,\n    'legend.fontsize': 7,\n    'figure.dpi': 300,\n    'savefig.dpi': 300,\n    'savefig.bbox': 'tight',\n    'savefig.pad_inches': 0.08,\n})\n\n# Primary: DeBERTa-MNLI across model x dataset at w=3\ndeberta_pts = [\n    (-36.76, 0.49, 'Qwen3-14B$_{\\\\mathrm{think}}$\\n(FOLIO)'),\n    (-33.82, 0.49, 'Qwen3-14B\\n(FOLIO)'),\n    (-30.83, 0.50, 'Qwen3-14B\\n(PW-D5)'),\n    (-19.00, 0.67, 'Qwen2.5-14B\\n(PW-D5)'),\n    (-6.37,  2.94, 'Mistral-7B\\n(FOLIO)'),\n    (15.67,  6.67, 'Mistral-7B\\n(ProofWriter)'),\n]\n\n# LLaMA point (different model family, separate marker)\nllama_pt = (-17.50, 0.83, 'LLaMA-8B\\n(PW-D5)')\n\n# Secondary: other NLI verifiers on Mistral-7B ProofWriter at w=3\nmulti_nli = [\n    (-1.66, 4.17, 'RoBERTa'),   # 37.67 - 39.33\n    (6.84,  5.17, 'BART'),       # 46.17 - 39.33\n]\n\n# Fine-tuned DeBERTa on ProofWriter OWA (99.67% standalone), w=3\nfinetuned_pts = [\n    (27.17, 11.67, 'LLaMA-8B'),    # 99.67 - 72.50 (finetuned SC)\n    (60.34, 12.67, 'Mistral-7B'),   # 99.67 - 39.33\n]\n\ndx = np.array([p[0] for p in deberta_pts])\ndy = np.array([p[1] for p in deberta_pts])\n\n# DeBERTa-only (excl. LLaMA) stats\nrho_excl, p_excl = spearmanr(dx, dy)\nprint(f\"DeBERTa-only (excl LLaMA) Spearman rho={rho_excl:.3f} (n={len(dx)}, p={p_excl:.4f})\")\n\n# All DeBERTa-verifier points (incl. LLaMA)\ndx_all = np.append(dx, llama_pt[0])\ndy_all = np.append(dy, llama_pt[1])\nrho, p_rho = spearmanr(dx_all, dy_all)\nprint(f\"DeBERTa-all (incl LLaMA) Spearman rho={rho:.3f} (n={len(dx_all)}, p={p_rho:.4f})\")\nslope, intercept, r_value, p_lin, _ = linregress(dx_all, dy_all)\nprint(f\"DeBERTa-all linear: R²={r_value**2:.3f}, p={p_lin:.4f}\")\n\n# Sigmoid with Director's parameters as guide\ndef sigmoid(x, L, k, x0, b):\n    return L / (1 + np.exp(-k * (x - x0))) + b\n\n# Use all points for visual fit (DeBERTa + LLaMA + multi-NLI)\nall_pts = deberta_pts + [llama_pt] + multi_nli\nax_all = np.array([p[0] for p in all_pts])\nay_all = np.array([p[1] for p in all_pts])\n\ntry:\n    popt, _ = curve_fit(sigmoid, ax_all, ay_all,\n                        p0=[3.5, 0.3, 1.0, 0.2],\n                        bounds=([0.5, 0.01, -10, -1], [5.0, 2.0, 15, 2.0]),\n                        maxfev=50000)\n    x_fit = np.linspace(-42, 68, 500)\n    y_sig = sigmoid(x_fit, *popt)\n    ss_res = np.sum((ay_all - sigmoid(ax_all, *popt))**2)\n    ss_tot = np.sum((ay_all - np.mean(ay_all))**2)\n    r2_sig = 1 - ss_res / ss_tot\n    inflection = popt[2]\n    print(f\"Sigmoid ({len(ax_all)}pt): R²={r2_sig:.3f}, inflection={inflection:.1f}pp, L={popt[0]:.2f}, k={popt[1]:.3f}\")\n    has_sigmoid = True\nexcept Exception as e:\n    print(f\"Sigmoid fit failed: {e}\")\n    has_sigmoid = False\n    x_fit = np.linspace(-42, 68, 500)\n\n# Plot\nfig, ax = plt.subplots(figsize=(3.8, 2.8))\nfig.subplots_adjust(left=0.16, bottom=0.20, right=0.96, top=0.94)\n\n# DeBERTa primary points (Mistral/Qwen generators)\nax.scatter(dx, dy, marker='o', c='#2166ac', s=50, zorder=5,\n           label='DeBERTa-MNLI', edgecolors='white', linewidths=0.5)\n\n# LLaMA generator (different model family)\nax.scatter([llama_pt[0]], [llama_pt[1]], marker='D', c='#e66101', s=50, zorder=5,\n           label='DeBERTa-MNLI (LLaMA)', edgecolors='white', linewidths=0.5)\n\n# Multi-NLI secondary points\nmx = [p[0] for p in multi_nli]\nmy = [p[1] for p in multi_nli]\nml = [p[2] for p in multi_nli]\nax.scatter([mx[0]], [my[0]], marker='s', c='#b2182b', s=40, zorder=5,\n           label='RoBERTa-MNLI', edgecolors='white', linewidths=0.5)\nax.scatter([mx[1]], [my[1]], marker='^', c='#4dac26', s=40, zorder=5,\n           label='BART-MNLI', edgecolors='white', linewidths=0.5)\n\n# Fine-tuned DeBERTa points\nfx = [p[0] for p in finetuned_pts]\nfy = [p[1] for p in finetuned_pts]\nax.scatter(fx, fy, marker='*', c='#7b3294', s=100, zorder=6,\n           label='Fine-tuned DeBERTa', edgecolors='white', linewidths=0.5)\n\n# Sigmoid curve\nif has_sigmoid:\n    ax.plot(x_fit, y_sig, '-', color='#555555', linewidth=1.0, alpha=0.6,\n            label=f'Sigmoid fit')\n\n# Annotations for DeBERTa points\nannot_config = [\n    (-36.76, 0.49, 'Qwen3-14B$_{\\\\mathrm{think}}$\\nFOLIO', (6, -3), 'left'),\n    (-35.29, 0.49, 'Qwen3-14B\\nFOLIO', (6, -15), 'left'),\n    (-30.83, 0.50, 'Qwen3-14B\\nPW-D5', (6, 3), 'left'),\n    (-19.00, 0.67, 'Qwen2.5-14B\\nPW-D5', (6, -8), 'left'),\n    (-6.37,  2.94, 'Mistral-7B\\nFOLIO', (6, -8), 'left'),\n    (15.67,  6.67, 'Mistral-7B\\nPW-D5', (-6, 5), 'right'),\n]\nfor x, y, lbl, offset, ha in annot_config:\n    ax.annotate(lbl, (x, y), textcoords='offset points',\n                xytext=offset, fontsize=5.5, ha=ha, color='#444444',\n                linespacing=0.9)\n\n# LLaMA annotation (distinct color)\nax.annotate('LLaMA-8B\\nPW-D5', (llama_pt[0], llama_pt[1]),\n            textcoords='offset points', xytext=(6, -10), fontsize=5.5,\n            ha='left', color='#e66101', linespacing=0.9)\n\n# Annotations for multi-NLI\nax.annotate('RoBERTa', (mx[0], my[0]), textcoords='offset points',\n            xytext=(5, 5), fontsize=5.5, ha='left', color='#b2182b')\nax.annotate('BART', (mx[1], my[1]), textcoords='offset points',\n            xytext=(5, 5), fontsize=5.5, ha='left', color='#4dac26')\n\n# Annotations for fine-tuned\nax.annotate('LLaMA-8B\\n(fine-tuned)', (fx[0], fy[0]), textcoords='offset points',\n            xytext=(-6, 5), fontsize=5.5, ha='right', color='#7b3294', linespacing=0.9)\nax.annotate('Mistral-7B\\n(fine-tuned)', (fx[1], fy[1]), textcoords='offset points',\n            xytext=(-6, 5), fontsize=5.5, ha='right', color='#7b3294', linespacing=0.9)\n\n# Reference lines\nax.axhline(0, color='black', linewidth=0.3, alpha=0.2)\nax.axvline(0, color='black', linewidth=0.5, alpha=0.25, linestyle=':')\n\n# Region labels\nax.text(-21, 14.0, 'verifier $<$ generator', fontsize=6.5, color='#aaaaaa',\n        ha='center', style='italic')\nax.text(40, 14.0, 'verifier $>$ generator', fontsize=6.5, color='#aaaaaa',\n        ha='center', style='italic')\n\nax.set_xlabel('Capability gap (verifier $-$ generator SC, pp)')\nax.set_ylabel('Combo gain over SC (pp, $w{=}3$)')\nax.set_xlim(-42, 68)\nax.set_ylim(-0.3, 15.0)\nax.legend(loc='lower right', framealpha=0.9, edgecolor='#cccccc',\n          borderpad=0.3, handletextpad=0.4, bbox_to_anchor=(1.0, 0.0))\nax.spines['top'].set_visible(False)\nax.spines['right'].set_visible(False)\n\n# no tight_layout — manual subplots_adjust above\noutdir = '/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/figures'\nfig.savefig(f'{outdir}/capability_gap_scatter.pdf')\nfig.savefig(f'{outdir}/capability_gap_scatter.png')\nprint(\"Saved to\", outdir)\n",
      "numLines": 182,
      "startLine": 1,
      "totalLines": 182
    }
  },
  "sourceToolAssistantUUID": "e2f630e2-d355-453f-9087-bad6b97591cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 50 · 2026-05-24T04:28:50.779Z_

<details open><summary>🔧 Tool call — Glob · `toolu_014XFVBtJZT2PBjwfvuYYAYo`</summary>

```json
{
  "pattern": "**/cross_arch.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dece1e11-0585-4270-b037-ac831c13c693",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "be909753-beda-4e93-8e10-aca3176f5a46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-24T04:28:50.791Z_

<details><summary>↩ Tool result · `toolu_014XFVBtJZT2PBjwfvuYYAYo`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "be909753-beda-4e93-8e10-aca3176f5a46",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "51ef9ce7-6ce7-4b2b-9379-3dd1483bfd11",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 8,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "be909753-beda-4e93-8e10-aca3176f5a46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 52 · 2026-05-24T04:28:57.303Z_

<details open><summary>🔧 Tool call — Bash · `toolu_018qqsEjiaqRwPNmRjEeSPZf`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt | python3 -c \"\nimport json, sys, yaml\n\ndata = json.load(sys.stdin)\nresult = data['result']\n# Parse the YAML content\nexperiments = yaml.safe_load(result)\n\n# Print experiment IDs and their metrics\nfor exp_id, exp in experiments.items():\n    metrics = exp.get('metrics', {})\n    if metrics:\n        print(f'=== {exp_id} ===')\n        print(f'  status: {exp.get(\\\"status\\\", \\\"?\\\")}')\n        for k, v in metrics.items():\n            print(f'  {k}: {v}')\n        print()\n\" 2>&1 | head -500",
  "description": "Extract experiment metrics from registry YAML",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "51ef9ce7-6ce7-4b2b-9379-3dd1483bfd11",
  "isSidechain": false,
  "requestId": "req_011CbLmD6iooJxcmsEqLgvdd",
  "type": "assistant",
  "uuid": "6bb0eab2-36c7-403c-8d8e-3aca84ce0431",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UouncZVfuHiAkB9rcHJKCM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 37971,
      "cache_read_input_tokens": 11841,
      "output_tokens": 774,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 37971,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 774,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 37971,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 37971
          },
          "type": "message"
        }
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
  "leafUuid": "6bb0eab2-36c7-403c-8d8e-3aca84ce0431",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Runtime record

_source line 54_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper numerics before submission deadline",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Tool result

_source line 55 · 2026-05-24T04:28:58.080Z_

<details><summary>↩ Tool result · `toolu_018qqsEjiaqRwPNmRjEeSPZf`</summary>

```text
Traceback (most recent call last):
  File "&lt;string>", line 11, in &lt;module>
    metrics = exp.get('metrics', {})
              ^^^^^^^
AttributeError: 'bool' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6bb0eab2-36c7-403c-8d8e-3aca84ce0431",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "f3041a70-a504-43c5-85fa-82f2c4952b97",
  "toolUseResult": {
    "stdout": "Traceback (most recent call last):\n  File \"&lt;string>\", line 11, in &lt;module>\n    metrics = exp.get('metrics', {})\n              ^^^^^^^\nAttributeError: 'bool' object has no attribute 'get'",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "6bb0eab2-36c7-403c-8d8e-3aca84ce0431",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Assistant

_source line 56 · 2026-05-24T04:29:00.889Z_

<details><summary>Logged reasoning block</summary>

```text
The registry parsing failed. Let me try a different approach to parse it. Let me also continue reading the appendix for the multi-seed table and other key data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f3041a70-a504-43c5-85fa-82f2c4952b97",
  "isSidechain": false,
  "requestId": "req_011CbLmEhnEPv3hkt1LDu7cE",
  "type": "assistant",
  "uuid": "8e610653-4479-4601-8cd7-c7c0baef5080",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKMHXMDnqqLePRBnkPLYyR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18083,
      "cache_read_input_tokens": 49812,
      "output_tokens": 406,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 18083,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 406,
          "cache_read_input_tokens": 49812,
          "cache_creation_input_tokens": 18083,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 18083
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-24T04:29:01.404Z_

Let me fix the registry parsing and read more appendix content.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8e610653-4479-4601-8cd7-c7c0baef5080",
  "isSidechain": false,
  "requestId": "req_011CbLmEhnEPv3hkt1LDu7cE",
  "type": "assistant",
  "uuid": "8b5d6cad-515c-47b9-ad0e-f28b2ee72cd6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKMHXMDnqqLePRBnkPLYyR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18083,
      "cache_read_input_tokens": 49812,
      "output_tokens": 406,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 18083,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 406,
          "cache_read_input_tokens": 49812,
          "cache_creation_input_tokens": 18083,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 18083
          },
          "type": "message"
        }
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

_source line 58 · 2026-05-24T04:29:06.632Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01LDsKX4U44HzkdpainpAWxw`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = data['result']\n# Check first 2000 chars to understand structure\nprint(result[:3000])\n\" 2>&1",
  "description": "Probe registry structure",
  "timeout": 15000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8b5d6cad-515c-47b9-ad0e-f28b2ee72cd6",
  "isSidechain": false,
  "requestId": "req_011CbLmEhnEPv3hkt1LDu7cE",
  "type": "assistant",
  "uuid": "674deafe-5347-4007-8bbd-eadacb7d81b7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKMHXMDnqqLePRBnkPLYyR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18083,
      "cache_read_input_tokens": 49812,
      "output_tokens": 406,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 18083,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 406,
          "cache_read_input_tokens": 49812,
          "cache_creation_input_tokens": 18083,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 18083
          },
          "type": "message"
        }
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

_source line 59 · 2026-05-24T04:29:06.722Z_

<details><summary>↩ Tool result · `toolu_01LDsKX4U44HzkdpainpAWxw`</summary>

```text
{"success": true, "data": {"experiments": {"exp-multi-seed-qwen25-pw-seed789-v2": {"status": "ANALYZING", "retry_count": 0, "created_at": "2026-05-23T04:10:25.973Z", "updated_at": "2026-05-24T04:01:31.277Z", "hypothesis": "Qwen2.5-14B PW seed789 多种子复制（第三次尝试，独立 vLLM on cuda:2 port 8007）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。前两次因 vLLM 配置问题失败。", "parent": "exp-multi-seed-qwen25", "spec": {"command": "python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8007 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen25_pw_seed789/results.json", "server": "westd-16639", "gpu": ["cuda:2"], "pid": "740841", "log_path": "~/runs/symb_invariant_consensus/exp-multi-seed-qwen25-pw-seed789-v2.log", "submitted_at": "2026-05-23T04:10:47.302Z", "submitted_via": "submit_training_job", "backend": "tmux", "account": "root", "data_path": "data/proofwriter_full.json", "data_count": 600, "model_name": "Qwen2.5-14B-Instruct", "seed": 789, "checkpoint_source": "vllm-served:/root/autodl-tmp/models/Qwen2.5-14B-Instruct", "eval_data": "data/proofwriter_full.json"}, "reproduce": {"finished_at": "2026-05-24T04:01:30.322Z"}}, "exp-multi-seed-llama-pw-seed789-v2": {"status": "DONE", "retry_count": 0, "created_at": "2026-05-23T05:56:24.810Z", "updated_at": "2026-05-23T20:37:24.235Z", "hypothesis": "LLaMA-3.1-8B PW seed789 多种子复制（westd-30973 cuda:1 全新运行）。替代 16639 cuda:0 上的慢速运行（12/600）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。", "parent": "exp-multi-seed-llama-pw", "spec": {"command": "bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8001 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/llama8b_pw_seed789_v2/results.json\"", "server": "westd-30973", "gpu": ["cuda:1"], "pid": "6018", "log_path": "~/runs/symb_invariant_consensus/exp-multi-seed-llama-pw-seed789-v2.log", "submitted_at": "2026-05-23T06:09:20.553Z", "submitted_via": "submit_training_job", "backend": "tmux", "account": "root", "data_path": "data/proofwriter_full.json", "data_count": 600, "model_name": "LLaMA-3.1-8B-Instruct", "seed": 789, "checkpoint_source": "vllm-served:/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct", "eval_data": "data/proofwriter_full.json", "checkpoint_path": "westd-16639:/root/symb_invariant_consensus/results/multi_seed/llama8b_pw_seed789/", "wall_clock_seconds": 52083.7, "gpu_hours": 14.47}, "notes": "冗余实验。seed789 完整结果在 westd-16639 (600/600, SC=71.17%, SICA=66.50% alphabetical corrected)。30973 上的 v2/v3 恢复进程已全部 kill。", "conclusion": "killed", "completed_at": "2026-05-23T20:37:24.235Z"}, "exp-multi-seed-qwen25-pw-seed789-v3": {"status": "DONE", "retry_count": 0, "created_at": "2026-05-23T05:56:23.947Z", "updated_at": "2026-05-23T20:34:39.605Z", "hypothesis": "Qwen2.5-14B PW seed789 多种子复制（westd-30973 cuda:0 全新运
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "674deafe-5347-4007-8bbd-eadacb7d81b7",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "2c8ec8d7-7a6a-4b32-ae03-cd192b733694",
  "toolUseResult": {
    "stdout": "{\"success\": true, \"data\": {\"experiments\": {\"exp-multi-seed-qwen25-pw-seed789-v2\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-23T04:10:25.973Z\", \"updated_at\": \"2026-05-24T04:01:31.277Z\", \"hypothesis\": \"Qwen2.5-14B PW seed789 多种子复制（第三次尝试，独立 vLLM on cuda:2 port 8007）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。前两次因 vLLM 配置问题失败。\", \"parent\": \"exp-multi-seed-qwen25\", \"spec\": {\"command\": \"python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8007 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/qwen25_pw_seed789/results.json\", \"server\": \"westd-16639\", \"gpu\": [\"cuda:2\"], \"pid\": \"740841\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-qwen25-pw-seed789-v2.log\", \"submitted_at\": \"2026-05-23T04:10:47.302Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-24T04:01:30.322Z\"}}, \"exp-multi-seed-llama-pw-seed789-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T05:56:24.810Z\", \"updated_at\": \"2026-05-23T20:37:24.235Z\", \"hypothesis\": \"LLaMA-3.1-8B PW seed789 多种子复制（westd-30973 cuda:1 全新运行）。替代 16639 cuda:0 上的慢速运行（12/600）。验证 SCB 在 ProofWriter 上跨 seed 稳定性。\", \"parent\": \"exp-multi-seed-llama-pw\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && python run_cross_dataset_replication.py --dataset proofwriter --data-path data/proofwriter_full.json --k 12 --vllm-port 8001 --seed 789 --temperature 0.7 --max-tokens 2048 --output results/multi_seed/llama8b_pw_seed789_v2/results.json\\\"\", \"server\": \"westd-30973\", \"gpu\": [\"cuda:1\"], \"pid\": \"6018\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-multi-seed-llama-pw-seed789-v2.log\", \"submitted_at\": \"2026-05-23T06:09:20.553Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 789, \"checkpoint_source\": \"vllm-served:/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/proofwriter_full.json\", \"checkpoint_path\": \"westd-16639:/root/symb_invariant_consensus/results/multi_seed/llama8b_pw_seed789/\", \"wall_clock_seconds\": 52083.7, \"gpu_hours\": 14.47}, \"notes\": \"冗余实验。seed789 完整结果在 westd-16639 (600/600, SC=71.17%, SICA=66.50% alphabetical corrected)。30973 上的 v2/v3 恢复进程已全部 kill。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-23T20:37:24.235Z\"}, \"exp-multi-seed-qwen25-pw-seed789-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T05:56:23.947Z\", \"updated_at\": \"2026-05-23T20:34:39.605Z\", \"hypothesis\": \"Qwen2.5-14B PW seed789 多种子复制（westd-30973 cuda:0 全新运",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "674deafe-5347-4007-8bbd-eadacb7d81b7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 60 · 2026-05-24T04:29:07.674Z_

<details open><summary>🔧 Tool call — Read · `toolu_0176YQTdaKPLhyEv8JRpoUJZ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
  "offset": 500,
  "limit": 500
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c8ec8d7-7a6a-4b32-ae03-cd192b733694",
  "isSidechain": false,
  "requestId": "req_011CbLmEhnEPv3hkt1LDu7cE",
  "type": "assistant",
  "uuid": "c6f24b29-6aae-47b7-b656-8e88955ff4e7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKMHXMDnqqLePRBnkPLYyR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18083,
      "cache_read_input_tokens": 49812,
      "output_tokens": 406,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 18083,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 406,
          "cache_read_input_tokens": 49812,
          "cache_creation_input_tokens": 18083,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 18083
          },
          "type": "message"
        }
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

_source line 61 · 2026-05-24T04:29:07.976Z_

<details><summary>↩ Tool result · `toolu_0176YQTdaKPLhyEv8JRpoUJZ`</summary>

```text
500	\addlinespace
501	24 & Atom pipeline & Paradigm & Decomposition & $-$10.0 & Atomic extraction degrades \\
502	25 & Premise-only filter & Constraint sel.\ & Bias isolation & $+$2.45 & $p = 0.359$; halves conclusion-bias \\
503	26 & DPP trace selection & Trace diversity & Determinantal & $+$1.47 & $p = 0.629$; $K_{\text{sel}}{=}8$ \\
504	27 & Z3 strict-mode & Solver config & UNSAT filtering & 0.0 & McNemar $b{=}1, c{=}1$; 63\% UNSAT \\
505	\bottomrule
506	\end{tabular}\\[2pt]
507	{\footnotesize All experiments on Mistral-7B FOLIO ($n{=}204$) unless noted. $^\dagger$\,Oscillates without convergence; net effect $\approx 0$. $^*$\,Accuracy gain only at reduced coverage (diagnostic value, not a general improvement). Methods 1--12 are reported in Table~\ref{tab:remediation} and Table~\ref{tab:method_interventions}.}
508	\end{table*}
509	
510	\begin{figure}[t]
511	\centering
512	\includegraphics[width=0.85\columnwidth]{figures/fig3_process_kappa_scatter.pdf}
513	\caption{Answer agreement vs.\ CoT cosine similarity (Mistral-7B, FOLIO, $n{=}204$). Flat regression ($r = -0.06$, $p = 0.36$); stronger models show significant positive correlation ($r = +0.24$, Qwen-14B; Table~\ref{tab:cross-model-process}).}
514	\label{fig:process-kappa}
515	\end{figure}
516	
517	
518	\section{Extraction Error Taxonomy}
519	\label{app:extraction}
520	\label{sec:extraction-taxonomy}
521	
522	Constraints must discriminate between candidate answers for MAX-SAT to produce a ranking different from majority vote. We measure discriminative power at two levels on Qwen2.5-14B across FOLIO and ProofWriter ($n = 804$). At the source-trace level, 39.2\% of total constraint weight originates from traces whose answer differs from the plurality, but only 12.1\% of individual constraints fall into this minority category. At the Z3 semantic level, 91.8\% of constraints [95\% CI: 91.2, 92.4] are technically discriminative, producing different satisfiability outcomes when evaluated against different candidate answers. Only 8.2\% are non-discriminative.
523	
524	The high discriminative rate does not translate into accuracy gains because discrimination mirrors the model's own answer distribution. Each trace produces constraints with its own variable names, so Z3 treats identically-intended propositions as unrelated symbols; among cross-answer constraint pairs, 56.4\% share zero Z3 variables. This variable isolation means constraints from different traces are trivially jointly satisfiable, and MAX-SAT retains nearly all of them regardless of source answer. Removing the 8.2\% non-discriminative constraints yields zero accuracy improvement. The discriminative majority does not provide independent signal; it reinforces the majority answer that SC would already select. This confirmation bias, not a lack of discrimination, explains why SICA degenerates to majority voting (Appendix~\ref{app:ablation}).
525	
526	
527	\section{Hyperparameter Sensitivity}
528	\label{app:sensitivity}
529	\label{sec:k-sensitivity}
530	\label{sec:t-sensitivity}
531	
532	\subsection{K Sensitivity}
533	
534	Figure~\ref{fig:k-sensitivity} shows SICA $\Delta$ as a function of the number of sampled traces $K$ for Mistral-7B on FOLIO ($n = 204$, no fixed seed). The relationship is non-monotonic: $K = 4$ yields $\Delta = -1.47$\,pp, $K = 8$ yields $\Delta = -1.96$\,pp, $K = 12$ reaches $\Delta = +3.43$\,pp, $K = 16$ drops to $\Delta = +1.47$\,pp, and $K = 20$ partially recovers to $\Delta = +1.96$\,pp. The recovery at $K = 20$ rules out a simple peaked pattern, but $K = 12$ remains the only setting with $\Delta > 2$\,pp ($p = 0.092$, marginal).
535	
536	The apparent $\Delta$ peak at $K = 12$ is confounded with SC baseline. SICA absolute accuracy plateaus at 59.31\% (121/204) for $K \geq 12$: identical at $K = 12$ and $K = 20$. The $\Delta$ variation across these settings is driven primarily by SC fluctuations rather than by SICA improvement. $K = 12$ produces a relatively low SC (55.88\%), placing it in the intermediate-SC region; $K = 8$ (SC $= 58.33\%$) and $K = 20$ (SC $= 57.35\%$) have higher baselines, compressing $\Delta$ even though SICA accuracy does not change for $K \geq 12$. Additional traces beyond $K = 12$ provide no benefit to SICA absolute performance, consistent with the constraint quality bottleneck. The $K = 12$ $\Delta$ captures only 25.0\% of the oracle ceiling ($+13.73$\,pp).
537	
538	\begin{figure}[h]
539	\centering
540	\includegraphics[width=\columnwidth]{f3_k_sensitivity}
541	\caption{SICA $\Delta$ (pp) vs.\ number of traces $K$ for Mistral-7B on FOLIO ($n = 204$, default seed, $T = 0.7$). Non-monotonic pattern: SICA accuracy plateaus at 59.31\% for $K \geq 12$; the apparent $\Delta$ peak at $K = 12$ partly reflects a relatively low SC baseline (55.88\%) at that point. Error bars: 95\% bootstrap CI.}
542	\label{fig:k-sensitivity}
543	\end{figure}
544	
545	\subsection{Temperature Sensitivity}
546	
547	Temperature sensitivity on Mistral-7B FOLIO ($n = 204$, default seed) reveals a sharp isolated peak rather than a smooth trend. Across four temperature settings, only $T = 0.7$ produces a positive effect: $T = 0.3$ yields $\Delta = -1.47$\,pp (SC $= 58.33\%$), $T = 0.5$ yields $\Delta = -0.98$\,pp (SC $= 58.33\%$), $T = 0.7$ yields $\Delta = +3.43$\,pp (SC $= 55.88\%$), and $T = 1.0$ yields $\Delta = 0.00$\,pp (SC $= 55.39\%$). All other temperatures yield negative or null effects, and the single positive result at $T = 0.7$ is confounded with SC baseline. Combined with the seed sensitivity (0 of 4 seeds reaching $p < 0.05$ at $T = 0.7$), the positive trend depends on a specific combination of temperature, seed, and baseline accuracy that same-model sampling rarely achieves.
548	
549	The parallel between $K$ and $T$ sensitivity points to a common underlying variable. In both sweeps, the setting that produces the largest SICA gain also produces a relatively low SC baseline (55.88\%), which places it in the intermediate-SC region. The hyperparameters themselves ($K$, $T$) are not the causal driver; they modulate SC level, and it is the SC level that determines whether SICA has operating room.
550	
551	
552	\section{Entropy Decomposition}
553	\label{app:entropy}
554	\label{sec:entropy}
555	
556	We partition problems by trace agreement: high-entropy (majority count $\leq 8$ out of $K = 12$) and low-entropy (majority count $\geq 9$). Table~\ref{tab:entropy} reports SICA $\Delta$ within each partition across eight model-dataset conditions.
557	
558	\begin{table}[h]
559	\centering
560	\small
561	\caption{Entropy decomposition of SICA $\Delta$ (pp). High-entropy: majority count $\leq 8$; low-entropy: majority count $\geq 9$. $^\dagger$Partial data (180/600). Pre-tiebreaking SC values; pattern robust to D064 correction.}
562	\label{tab:entropy}
563	\begin{tabular}{@{}llrrrr@{}}
564	\toprule
565	Model & Dataset & \multicolumn{2}{c}{High-entropy} & \multicolumn{2}{c}{Low-entropy} \\
566	\cmidrule(lr){3-4} \cmidrule(lr){5-6}
567	 & & $n$ & $\Delta$ & $n$ & $\Delta$ \\
568	\midrule
569	Mistral-7B & FOLIO & 78 & $\mathbf{+12.8}$ & 126 & 0.0 \\
570	Mistral-7B (s123) & FOLIO & 77 & $\mathbf{+9.1}$ & 127 & 0.0 \\
571	Mistral-7B (s456) & FOLIO & 75 & $-$1.3 & 129 & 0.0 \\
572	Mistral-7B & PW-D5 & 267 & $-$4.9 & 333 & $-$1.2 \\
573	Qwen2.5-14B & FOLIO & 37 & $-$8.2 & 167 & $-$0.6 \\
574	Qwen2.5-14B & LogiQA & 23 & $-$4.3 & 177 & 0.0 \\
575	Qwen2.5-7B & FOLIO & 47 & $-$2.1 & 157 & 0.0 \\
576	LLaMA-3.1-8B$^\dagger$ & PW-D5 & 76 & $-$3.9 & 104 & $-$1.9 \\
577	\bottomrule
578	\end{tabular}
579	\end{table}
580	
581	Two patterns emerge. First, low-entropy problems produce $\Delta \approx 0$\,pp across all eight conditions: when traces agree, constraints carry no information beyond the majority vote.
582	
583	Second, the direction of SICA's effect on high-entropy problems depends on the accuracy regime, not on entropy alone. In the intermediate-SC region (Mistral-7B on FOLIO, default-seed and seed-123 runs), high-entropy $\Delta$ reaches $+12.8$ and $+9.1$\,pp: traces genuinely disagree, and constraints from correct-answer traces provide discriminative signal that resolves the disagreement. In Type~A conditions (Qwen2.5-14B on FOLIO, $\Delta = -8.2$\,pp), high-entropy problems represent rare deviations from a strong model's consensus; constraints inherit the model's confirmation bias. In Type~C (Mistral-7B on ProofWriter, $\Delta = -4.9$\,pp), high-entropy problems reflect systematic errors. The mechanism is not entropy per se but the interaction of entropy with model capability.
584	
585	
586	\section{Failure Mode Analysis}
587	\label{app:failure-modes}
588	\label{sec:failure-modes}
589	
590	The regime-dependent pattern in Table~\ref{tab:main_results} reflects three distinct failure modes of self-extracted logical constraints.
591	
592	\paragraph{Type A: confirmation bias (SC $\geq$ $\sim$60\%).} Strong models produce consistent reasoning traces, and constraints extracted from those traces mirror the answer distribution. When most constraints support the same candidate, MAX-SAT excludes few clauses ($|\mathcal{C}^{\setminus}| \approx 0$), the penalty term in Eq.~\ref{eq:score} vanishes, and the scoring function degenerates to weighted vote counting (Eq.~\ref{eq:degenerate}). SICA and SC then produce identical predictions. The ablation in Appendix~\ref{app:ablation} confirms this empirically: on Qwen2.5-14B (FOLIO + ProofWriter, $n = 804$), MAX-SAT and count-only baselines agree on 803 of 804 predictions.
593	
594	\paragraph{Type B: non-formalizable domains.} LogiQA problems require pragmatic and contextual reasoning that resists clean logical formalization. Qwen2.5-14B on LogiQA achieves an extraction rate of 86.4\%, but the resulting constraints have a contradiction rate of only 0.8\%: extracted formulas rarely conflict across traces, leaving MAX-SAT with no logical tension to exploit. Mistral-7B on LogiQA sits in the same SC range (50.00\%) yet produces $\Delta = +1.50$\,pp ($p = 0.581$); Qwen2.5-14B on the same domain yields $\Delta = -1.00$\,pp ($p = 0.625$). Neither model benefits, confirming that the right accuracy regime is necessary but not sufficient when the domain resists formalization.
595	
596	\paragraph{Type C: error amplification (SC $\leq$ $\sim$40\%).} When model accuracy is low, the majority of traces reach incorrect answers. Constraints extracted from wrong traces encode incorrect reasoning as formal rules. Z3 treats these rules as soft clauses with weight proportional to their frequency, so the solver preferentially satisfies the wrong constraints and penalizes traces that happen to reach the correct answer. Mistral-7B on ProofWriter ($\Delta = -2.83$\,pp, raw $p = 0.014$; BH adj.\ $p = 0.066$) demonstrates this effect: SICA converts a weak positive signal in trace diversity into a net negative by formalizing the errors.
597	
598	
599	\section{Cross-Model Confirmation Bias}
600	\label{app:cross-model-bias}
601	
602	Table~\ref{tab:cross-model-bias} reports MaxSAT-weighted confirmation bias metrics across three model families on FOLIO ($n = 204$). Weighted bias ratio and wrong-supporting constraint percentage both decrease with model capability, while SICA's accuracy effect shifts from positive (Mistral, intermediate-SC regime) to negative (LLaMA, high-SC regime). Raw bias ratios ($4.97\times$, $3.85\times$, $2.88\times$) are reported in \S\ref{sec:confirmation-bias}. LLaMA weighted BR CI: [2.19, 3.28].
603	
604	\begin{table}[h]
605	\centering
606	\small
607	\caption{Cross-model confirmation bias on FOLIO ($n = 204$, $K = 12$). BR (wtd.): MaxSAT-weighted ratio of error-supporting constraints on incorrect vs.\ correct problems. Wrong \%: weighted fraction of constraints supporting the incorrect majority on error problems. $\Delta$: SICA $-$ SC (pp).}
608	\label{tab:cross-model-bias}
609	\begin{tabular}{@{}lrrr@{}}
610	\toprule
611	Model & BR (wtd.) & Wrong (\%) & $\Delta$ (pp) \\
612	\midrule
613	Mistral-7B & $4.24\times$ & 80.9 & $+$4.90 \\
614	Qwen2.5-14B & $3.69\times$ & 78.7 & $-$0.98 \\
615	LLaMA-3.1-8B & $2.66\times$ & 72.7 & $-$4.41 \\
616	\bottomrule
617	\end{tabular}
618	\end{table}
619	
620	\paragraph{Frontier model universality.}
621	\label{app:frontier-scb}
622	Table~\ref{tab:frontier-scb} (main text, \S\ref{sec:confirmation-bias}) extends confirmation bias analysis to nine models spanning 7B open-source to frontier closed-source. All models exhibit $\text{BR} > 1$ (range: $1.66$--$4.97\times$). Extraction context varies: open-source models use self-extraction (the model extracts constraints from its own traces); frontier models use cross-model extraction (Mistral-7B extracts FOL from the target model's traces), as closed-source APIs do not expose internal representations suitable for direct symbolic extraction.
623	
624	\paragraph{ProcessSim definition.}
625	\label{app:process-sim}
626	Process similarity is the mean pairwise cosine similarity of TF-IDF trace representations:
627	\begin{equation}
628	\label{eq:process-sim}
629	\text{ProcessSim}(q) = \frac{2}{K(K{-}1)} \sum_{i < j} \cos(\mathbf{v}_i^q, \mathbf{v}_j^q),
630	\end{equation}
631	where $\mathbf{v}_i^q$ is the TF-IDF vector of trace $t_i$ for question $q$.
632	
633	\paragraph{Process-$\kappa$ gradient.}
634	\label{app:process-gradient}
635	Under cross-model extraction (Mistral-7B extracts FOL from other models' traces), SICA gain decreases monotonically with process-level cosine similarity (Table~\ref{tab:process-gradient}; Spearman $\rho = -1.0$, $n = 5$, one-tailed $p = 0.0083$). Gain requires two conditions: diverse traces (low $\kappa_{\text{proc}}$) \emph{and} substantial self-bias (high BR). R1-Distill-8B satisfies both ($\kappa_{\text{proc}} = 0.248$, $\text{BR} = 2.92$) and gains $+2.45$\,pp; o3 has moderate trace diversity ($\kappa_{\text{proc}} = 0.596$) but near-minimal bias ($\text{BR} = 1.66$, exhibiting a bimodal error pattern: 82\% of error problems have $\text{BR} = \infty$ but low finite-BR), yielding $\Delta = 0$.
636	
637	\begin{table}[h]
638	\centering
639	\small
640	\caption{Process-$\kappa$ gradient under cross-model extraction (Mistral-7B $\rightarrow$ target model traces, FOLIO). $\kappa_{\text{proc}}$: process-level cosine similarity. $\Delta$: SICA $-$ SC (pp). Spearman $\rho(\kappa_{\text{proc}} \rightarrow \Delta) = -1.0$, $p = 0.0083$. $^*$Interim ($n = 95/204$).}
641	\label{tab:process-gradient}
642	\begin{tabular}{@{}lrrr@{}}
643	\toprule
644	Model & $\kappa_{\text{proc}}$ & $\Delta$ (pp) & BR \\
645	\midrule
646	R1-Distill-8B & 0.248 & $+$2.45 & 2.92 \\
647	gpt-5.5 & 0.563 & $+$0.49 & 3.48 \\
648	o3 & 0.596 & 0.00 & 1.66 \\
649	Gemini-2.5-Pro$^*$ & 0.790 & $-$1.05 & 2.79 \\
650	gpt-4.1 & 0.792 & $-$1.47 & 2.70 \\
651	\bottomrule
652	\end{tabular}
653	\end{table}
654	
655	
656	\section{Independence-Accuracy Scatter Plot}
657	\label{app:kappa-scatter}
658	
659	\begin{figure}[h]
660	\centering
661	\includegraphics[width=\columnwidth]{figures/f6_kappa_accuracy_scatter}
662	\caption{Independence-accuracy trade-off across aggregation methods (Mistral-7B, filled markers) and model families (LLaMA-3.1-8B, Qwen2.5-7B, Qwen2.5-14B; open markers) on FOLIO ($n = 204$). Same-model methods cluster at $\kappa \approx 0.40$--$0.47$ (gray band), while cross-model SC shows stronger correlations ($\kappa = 0.41$--$0.74$) at higher accuracy. Debate breaks correlation ($\kappa = 0.15$) at catastrophic accuracy cost. Dashed line: Mistral-7B SC baseline.}
663	\label{fig:kappa-accuracy}
664	\end{figure}
665	
666	\begin{table}[h]
667	\centering
668	\small
669	\caption{Independence-accuracy trade-off (FOLIO, $n = 204$). Top: aggregation methods on Mistral-7B; bottom: SC across three model families. All families produce $\kappa \geq 0.41$, confirming an architecture-independent ceiling. $\kappa$: Fleiss' kappa on raw answers.}
670	\label{tab:kappa_generalization}
671	\setlength{\tabcolsep}{3.5pt}
672	\begin{tabular}{@{}llccrr@{}}
673	\toprule
674	Model & Aggregation & $\kappa$ & Eff-$K$ & $K$ & Acc.\ (\%) \\
675	\midrule
676	Mistral-7B & Debate & 0.15 & 4.44 & 12 & 38.24 \\
677	& Diverse-Prompt & 0.40 & 2.21 & 12 & 54.41 \\
678	& Self-Consistency & 0.44 & 2.02 & 10 & 56.86 \\
679	& ICG & 0.47 & 1.93 & 10 & 51.96 \\
680	\addlinespace
681	LLaMA-3.1-8B & Self-Consistency & 0.41 & 2.17 & 12 & 66.18 \\
682	Qwen2.5-7B & Self-Consistency & 0.66 & 1.46 & 12 & 75.98 \\
683	Qwen2.5-14B & Self-Consistency & 0.74 & 1.32 & 12 & 75.98 \\
684	\bottomrule
685	\end{tabular}
686	\end{table}
687	
688	\paragraph{Trace independence metrics.}
689	\label{app:trace-independence}
690	
691	Table~\ref{tab:independence} reports the full 15-condition breakdown of Fleiss' $\kappa$ and Effective-K at $K = 12$, referenced in \S\ref{sec:effective-k}.
692	
693	\begin{table}[h]
694	\centering
695	\small
696	\setlength{\tabcolsep}{3pt}
697	\caption{Trace independence metrics ($K = 12$, sorted by $\kappa$ descending). $\kappa$: Fleiss' Kappa. $K_{\text{eff}}$: Effective-K (Eq.~\ref{eq:effk}). SC: Self-Consistency baseline. $\Delta$: SICA $-$ SC (pp). {*}\,$p < 0.05$ (uncorrected; BH adj.\ $p = 0.066$, $m{=}6$); positive $\Delta$ values do not reach significance. multi-T $= T \in \{0.3, 0.7, 1.2\}$, 4 traces each.}
698	\label{tab:independence}
699	\begin{tabular}{@{}llccrr@{}}
700	\toprule
701	Model & Condition & $\kappa$ & $K_{\text{eff}}$ & SC (\%) & $\Delta$ (pp) \\
702	\midrule
703	Qwen3 (think) & FOLIO & 0.91 & 1.09 & 86.27 & $+$0.49 \\
704	Qwen2.5-14B & LogiQA & 0.82 & 1.20 & 79.00 & $-$1.00 \\
705	Qwen3 & FOLIO & 0.77 & 1.26 & 83.33 & $+$1.47 \\
706	Qwen2.5-14B & FOLIO & 0.74 & 1.30 & 75.98 & $-$0.49 \\
707	Qwen2.5-7B & FOLIO & 0.66 & 1.46 & 75.98 & $+$0.49 \\
708	\addlinespace
709	Mistral-7B ($T{=}0.3$) & FOLIO & 0.53 & 1.77 & 58.33 & $-$1.47 \\
710	Mistral-7B & LogiQA & 0.51 & 1.81 & 50.00 & $+$1.50 \\
711	Mistral-7B (s456) & FOLIO & 0.51 & 1.82 & 55.88 & 0.00 \\
712	Mistral-7B & FOLIO & 0.50 & 1.84 & 55.88 & $+$3.43 \\
713	Mistral-7B (s123) & FOLIO & 0.49 & 1.88 & 54.41 & $+$2.94 \\
714	Mistral-7B (s789) & FOLIO & 0.45 & 2.03 & 59.31 & $-$2.45 \\
715	Mistral-7B ($T{=}0.5$) & FOLIO & 0.52 & 1.80 & 58.33 & $-$0.98 \\
716	Mistral-7B (multi-T) & FOLIO & 0.48 & 1.91 & 57.84 & 0.00 \\
717	Mistral-7B ($T{=}1.0$) & FOLIO & 0.48 & 1.91 & 55.39 & 0.00 \\
718	Mistral-7B & PW-D5 & 0.21 & 3.62 & 39.33 & $\mathbf{-2.83}${*} \\
719	\bottomrule
720	\end{tabular}
721	\end{table}
722	
723	\section{Cross-Model Kappa Analysis}
724	\label{app:cross-model-kappa}
725	
726	Table~\ref{tab:cross_model_kappa} compares trace independence across three model families on the same benchmarks. On FOLIO ($n = 204$), all four models produce $\kappa \geq 0.41$: LLaMA-3.1-8B ($\kappa = 0.41$), Mistral-7B ($\kappa = 0.44$), Qwen2.5-7B ($\kappa = 0.66$), and Qwen2.5-14B ($\kappa = 0.74$). The bottleneck is architecture-independent---no family escapes the correlation floor. Within the Qwen family, $\kappa$ increases from 0.66 (7B) to 0.74 (14B), but Mistral-7B (7B) and LLaMA-3.1-8B (8B) differ by $\Delta\kappa = 0.03$ despite belonging to different families, suggesting that cross-family variation ($\Delta\kappa$ up to 0.22 at similar scale) exceeds within-family scale effects ($\Delta\kappa = 0.08$). Disentangling scale from architecture requires controlled same-family experiments across $\geq$3 scales.
727	
728	\begin{table}[h]
729	\centering
730	\small
731	\caption{Cross-model trace independence ($K = 12$, SC aggregation, FOLIO + ProofWriter). Higher $\kappa$ indicates stronger correlation and lower effective sample size.}
732	\label{tab:cross_model_kappa}
733	\begin{tabular}{@{}llccr@{}}
734	\toprule
735	Model & Dataset & $\kappa$ & $K_{\text{eff}}$ & SC (\%) \\
736	\midrule
737	Qwen2.5-14B & FOLIO & 0.74 & 1.32 & 75.98 \\
738	Qwen2.5-7B & FOLIO & 0.66 & 1.46 & 75.98 \\
739	Mistral-7B & FOLIO & 0.44 & 2.02 & 56.86 \\
740	LLaMA-3.1-8B & FOLIO & 0.41 & 2.17 & 66.18 \\
741	\addlinespace
742	Qwen2.5-14B & PW-D5 & 0.62 & 1.54 & --- \\
743	Mistral-7B & PW-D5 & 0.21 & 3.62 & 39.33 \\
744	\bottomrule
745	\end{tabular}
746	\end{table}
747	
748	
749	\section{Cross-Model Process-Level Independence}
750	\label{app:cross-model-process}
751	
752	Table~\ref{tab:cross-model-process} extends the process-level independence analysis (\S\ref{sec:process-kappa}) to four model families on FOLIO ($n = 204$). Mean pairwise cosine similarity of TF-IDF trace representations exceeds answer-level $\kappa$ in every family, but the gap is model-strength dependent: it narrows from $0.31$ (LLaMA) and $0.23$ (Mistral) to $0.02$ (Qwen-14B). For weaker models ($r \approx 0$), answer diversity does not reflect reasoning diversity---process-convergent but answer-divergent trace pairs constitute 9.5\% of all pairs on Mistral-7B versus 2.5--3.2\% on other families. For stronger models ($r \approx 0.23$, $p \leq 0.001$), process and answer agreement align, and answer-level $\kappa$ already captures the bottleneck. Process-$\kappa$ thus provides a crucial additional diagnostic specifically for weaker models, where answer-level metrics underestimate reasoning homogeneity.
753	
754	\begin{table}[h]
755	\centering
756	\small
757	\caption{Cross-model process-level independence on FOLIO ($n = 204$, $K = 12$). Mean Cosine: mean pairwise TF-IDF cosine similarity of reasoning traces (Eq.~\ref{eq:process-sim}). Answer $\kappa$: per-question answer agreement. Gap: Cosine $-$ $\kappa$. $r$: Pearson correlation between ProcessSim and answer agreement. Conv.: fraction of process-convergent but answer-divergent trace pairs. {*}{*}\,$p < 0.01$; {*}{*}{*}\,$p < 0.001$.}
758	\label{tab:cross-model-process}
759	\resizebox{\columnwidth}{!}{%
760	\begin{tabular}{@{}lcccrlr@{}}
761	\toprule
762	Model & Mean Cos. & Ans.\ $\kappa$ & Gap & $r$ & $p$ & Conv.\ (\%) \\
763	\midrule
764	Mistral-7B & 0.690 & 0.460 & 0.230 & $-$0.064 & 0.362 & 9.5 \\
765	LLaMA-3.1-8B & 0.759 & 0.447 & 0.312 & $-$0.001 & 0.985 & 3.2 \\
766	Qwen2.5-7B & 0.790 & 0.658 & 0.132 & $+$0.226 & 0.001{*}{*} & 2.8 \\
767	Qwen2.5-14B & 0.766 & 0.744 & 0.022 & $+$0.244 & ${<}$0.001{*}{*}{*} & 2.5 \\
768	\bottomrule
769	\end{tabular}}
770	\end{table}
771	
772	\paragraph{Representation robustness.} Replacing TF-IDF with SBERT embeddings (all-MiniLM-L6-v2) yields ProcessSim $= 0.91$ (vs.\ TF-IDF $0.74$), widening the gap over answer-level $\kappa = 0.55$. The process homogeneity finding is robust to representation choice.
773	
774	\section{Constraint Quality Across Methods}
775	\label{app:constraint-quality}
776	
777	Table~\ref{tab:constraint_quality} compares constraint quality metrics across the three method-level interventions on Mistral-7B FOLIO ($n = 204$). Standard SICA extracts from reasoning traces and achieves the highest parse rate (97.1\%) but also the highest redundancy (42.9\%): nearly half of all constraints are syntactic duplicates across the 12 traces, quantifying the co-sourcing effect of same-model generation. ICG generates constraints directly from the problem statement without trace conditioning. Its lower parse rate (74.6\%) reflects the difficulty of standalone formalization at the 7B scale, though successfully parsed constraints compile at a higher rate (99.4\% vs.\ 96.5\%). ICG produces fewer unique constraints per question (24.9 vs.\ 39.3) with lower redundancy (32.3\%), consistent with the absence of trace-level repetition. Contrastive scoring generates pro and con constraint sets for each candidate answer. The format yields far fewer unique constraints per question (9.2) with zero redundancy (each pro/con pair is structurally distinct), but 62.7\% of constraints are trivially satisfied by Z3---they impose no logical tension and cannot discriminate between candidates. Only 51.0\% of Contrastive constraints are discriminative, compared to 81.4\% for standard SICA and 77.0\% for ICG.
778	
779	\begin{table}[h]
780	\centering
781	\small
782	\caption{Constraint quality metrics across method-level interventions (Mistral-7B, FOLIO, $n = 204$). Parse: fraction of extraction attempts yielding valid JSON. Z3 Compile: fraction compiling to Z3 formulas. Unique/q: mean unique constraints per question. Redundancy: fraction of constraints duplicated across traces. Disc.: fraction discriminative (different Z3 outcome per candidate). Triv.\ Sat.: fraction trivially satisfied (no logical tension).}
783	\label{tab:constraint_quality}
784	\resizebox{\columnwidth}{!}{%
785	\begin{tabular}{@{}l rrrrrr@{}}
786	\toprule
787	Method & Parse & Z3 & Uniq/q & Redund. & Disc. & Triv.\ Sat. \\
788	\midrule
789	Standard SICA & 97.1\% & 96.5\% & 39.3 & 42.9\% & 81.4\% & --- \\
790	ICG & 74.6\% & 99.4\% & 24.9 & 32.3\% & 77.0\% & --- \\
791	Contrastive & 74.0\% & 94.4\% & 9.2 & 0.0\% & 51.0\% & 62.7\% \\
792	\bottomrule
793	\end{tabular}}
794	\end{table}
795	
796	\paragraph{Per-trace constraint yield uniformity.}
797	\label{app:yield-cv}
798	
799	Observation~1 assumes approximately uniform constraint yield per trace within each answer group. We verify this on Mistral-7B FOLIO ($K{=}12$, $n{=}204$). Per-problem yield CV (coefficient of variation across traces within each problem) has median $0.257$ and mean $0.319$; 64.2\% of problems fall below $\text{CV} = 0.3$, and 91.2\% below $0.5$, supporting the uniformity assumption. Majority-answer traces average $5.61$ constraints and minority-answer traces $6.04$ (Mann--Whitney $p = 5.2 \times 10^{-6}$); correct-answer traces average $5.41$ and incorrect $6.05$ ($p = 5.3 \times 10^{-11}$). Although statistically significant, the absolute difference (${\sim}0.6$ constraints, $< 12\%$) is insufficient to alter the argmax-preservation result: SICA and SC select the same answer on ${>}96\%$ of problems regardless of yield variation.
800	
801	\section{Error Categorization of Method-Level Interventions}
802	\label{app:error-categorization}
803	
804	We categorize discordant predictions (where the method and SC disagree) for Debate and Contrastive on FOLIO ($n = 204$) to understand why these interventions degrade accuracy.
805	
806	\paragraph{Debate discordant analysis.} Debate produces 60 correct$\to$wrong flips and 22 wrong$\to$correct flips on FOLIO. Answer-type breakdown reveals that False-labeled questions are most vulnerable: 82.8\% of False questions that SC answers correctly are flipped by Debate, compared to 63.9\% for True and 25.5\% for Unknown. Counterintuitively, failures concentrate not where debate breaks down but where it succeeds most thoroughly: discordant questions average 2.93 effective debate rounds (proposer-critic exchanges producing substantive updates) versus 2.52 for concordant ones. More extensive same-model debate produces more confident but incorrect constraints, consistent with the independence limitation---the critic draws on the same model distribution as the proposer, reinforcing shared biases rather than correcting them.
807	
808	\paragraph{Contrastive discordant analysis.} Contrastive produces 34 discordant questions on FOLIO. All 34 produced non-degenerate scores (both pro and con constraint sets non-empty), compared to 20.1\% degenerate scores in the full sample. This indicates that scoring failures on discordant questions stem from systematic pro-bias rather than missing constraints. Among discordant questions, 97.1\% contain negation words in the problem statement versus 76.5\% in the full sample, suggesting that negation-bearing problems are particularly susceptible to pro-constraint imbalance. The average pro/con score ratio is 1.0 for discordant questions versus 0.68 for the full sample: the method generates balanced-looking scores that mask directional errors.
809	
810	\paragraph{Cross-method overlap.} Of the 79 unique questions on which either method disagrees with SC, only 15 overlap between Debate and Contrastive (Jaccard index $= 0.19$). All 15 shared discordant questions contain negation words. The low overlap confirms that the two methods attack different vulnerability types---Debate through extended same-model argumentation that amplifies confident errors, Contrastive through pro-bias in constraint generation---while sharing a common root cause in correlated same-model voting: both methods rely on the same model's output distribution and cannot introduce genuinely independent signal.
811	
812	
813	\section{TOST Equivalence Tests}
814	\label{app:tost}
815	
816	We apply two one-sided tests (TOST) \citep{lakens2017equivalence} with equivalence margin $\pm 2$\,pp to all 16 non-degenerate SICA--SC comparisons, classifying each condition as \emph{equivalent} (TOST significant), \emph{genuinely different} (McNemar $p < 0.05$ and TOST not significant), or \emph{underpowered} (neither test significant). Four conditions are equivalent, confirming that SICA and SC produce statistically indistinguishable accuracy. Two conditions show genuine differences, both negative: Mistral-7B ProofWriter ($-2.83$\,pp, $p = 0.014$) and Qwen2.5-14B ProofWriter ($-2.50$\,pp, $p = 0.011$). The remaining ten conditions are underpowered, reflecting the limited statistical power at $n{=}200$--$204$ for detecting $|\Delta| \leq 2$\,pp effects.
817	
818	\paragraph{Margin sensitivity.} Table~\ref{tab:tost-sensitivity} shows that the classification is robust across margins: regardless of the chosen margin, no condition shows a significant positive SICA effect.
819	
820	\begin{table}[h]
821	\centering
822	\small
823	\caption{TOST classification sensitivity across equivalence margins (16 non-degenerate conditions).}
824	\label{tab:tost-sensitivity}
825	\begin{tabular}{@{}lccc@{}}
826	\toprule
827	Margin & Equivalent & Different & Underpowered \\
828	\midrule
829	$\pm 1$\,pp & 0 & 2 & 14 \\
830	$\pm 2$\,pp & 4 & 2 & 10 \\
831	$\pm 3$\,pp & 10 & 0 & 6 \\
832	\bottomrule
833	\end{tabular}
834	\end{table}
835	
836	\paragraph{Relative-margin TOST.}
837	\label{app:relative_tost}
838	The absolute $\pm 2$\,pp margin is more stringent at high baselines ($\pm 2.4\%$ relative at SC $= 85\%$) than low ones ($\pm 5.1\%$ at SC $= 39\%$). A relative $\pm 5\%$ of SC margin addresses this asymmetry: 8 conditions are equivalent, 2 genuinely different (both negative), and 6 underpowered. The additional four equivalent conditions are all high-SC ($\geq 75\%$), where the wider relative band captures practical indistinguishability. No condition shows a significant positive effect under either margin.
839	
840	\paragraph{Conditional Correction Ratio data.}
841	\label{app:cil-data}
842	
843	\begin{table}[h]
844	\centering
845	\small
846	\setlength{\tabcolsep}{3pt}
847	\caption{Conditional Correction Ratio across eight verifier--generator conditions. $\text{CCR} > 0$: cross-arch NLI on ProofWriter. $\text{CCR} < 0$: same-model SICA or weak capability gap.}
848	\label{tab:cil_main}
849	\begin{tabular}{@{}llrr@{}}
850	\toprule
851	Generator--Verifier & Dataset & CCR & $\Delta$ (pp) \\
852	\midrule
853	Mistral $\times$ BART-NLI & PW & $+$1.86 & $+$5.17 \\
854	Mistral $\times$ DeBERTa-NLI & PW & $+$1.67 & $+$6.67 \\
855	Mistral $\times$ RoBERTa-NLI & PW & $+$1.42 & $+$4.17 \\
856	\addlinespace
857	Qwen-14B $\times$ DeBERTa-NLI & PW & $-$0.21 & $+$0.33 \\
858	Mistral $\times$ DeBERTa-NLI & FOLIO & $-$0.47 & $+$2.94 \\
859	\addlinespace
860	Mistral $\times$ SICA & FOLIO & $-$2.93 & $+$3.43 \\
861	Qwen-14B $\times$ SICA & PW & $-$4.21 & $-$2.50 \\
862	Mistral $\times$ SICA & PW & $-$4.61 & $-$2.83 \\
863	\bottomrule
864	\end{tabular}
865	\end{table}
866	
867	\paragraph{Disagreement-Routed Cascade details.}
868	\label{app:drc}
869	DRC invokes NLI only when SC consensus falls below threshold $\tau$, avoiding unnecessary verifier calls on high-agreement problems. Gains concentrate on weak generators (SC $< 40\%$), consistent with the capability-gap hypothesis (\S\ref{sec:cross-arch}). Regime-dependent bottleneck analysis appears in Appendix~\ref{app:2x2}.
870	
871	\begin{table}[h]
872	\centering
873	\small
874	\caption{DRC on Mistral-7B ($K{=}12$, DeBERTa-large-mnli, $w{=}3$). $\tau{=}0.7$ recovers 83--90\% of full-combo gain at ${\sim}35\%$ NLI cost across both datasets.}
875	\label{tab:drc}
876	\setlength{\tabcolsep}{3pt}
877	\begin{tabular}{@{}llcccc@{}}
878	\toprule
879	Dataset & Method & Acc.\ & NLI Calls & Cost & Recovery \\
880	\midrule
881	\multirow{3}{*}{PW-D5} & SC only & 39.33\% & 0/600 & 0\% & --- \\
882	& \textbf{DRC $\tau{=}0.7$} & \textbf{45.33\%} & \textbf{207/600} & \textbf{34.5\%} & \textbf{90.0\%} \\
883	& Full combo & 46.00\% & 600/600 & 100\% & 100\% \\
884	\midrule
885	\multirow{3}{*}{FOLIO} & SC only & 55.88\% & 0/204 & 0\% & --- \\
886	& \textbf{DRC $\tau{=}0.7$} & \textbf{58.33\%} & \textbf{71/204} & \textbf{34.8\%} & \textbf{83.3\%} \\
887	& Full combo & 58.82\% & 204/204 & 100\% & 100\% \\
888	\bottomrule
889	\end{tabular}
890	\end{table}
891	
892	\section{Multi-Verifier NLI Results}
893	\label{app:multi-nli}
894	
895	\begin{table}[h]
896	\centering
897	\small
898	\caption{Cross-architecture NLI combo on ProofWriter depth-5 ($n{=}600$, Mistral-7B traces, SC $= 39.33\%$). Three NLI verifiers $\times$ three weight settings. {*}\,$p < 0.05$;\enspace{**}\,$p < 0.01$;\enspace{***}\,$p < 0.001$ (McNemar).}
899	\label{tab:multi-nli}
900	\begin{tabular}{@{}llrrl@{}}
901	\toprule
902	Verifier & Standalone & $w$ & $\Delta$ (pp) & $p$ \\
903	\midrule
904	DeBERTa-MNLI & 55.00\% & 1 & $+$0.83 & n.s. \\
905	 & & 3 & $+$6.67 & ${<}0.001${***} \\
906	 & & 5 & $+$11.00 & ${<}0.001${***} \\
907	\addlinespace
908	RoBERTa-MNLI & 37.67\% & 1 & $-$0.17 & n.s. \\
909	 & & 3 & $+$4.17 & 0.003{**} \\
910	 & & 5 & $+$4.33 & 0.037{*} \\
911	\addlinespace
912	BART-MNLI & 46.17\% & 1 & 0.00 & n.s. \\
913	 & & 3 & $+$5.17 & ${<}0.001${***} \\
914	 & & 5 & $+$6.33 & 0.003{**} \\
915	\bottomrule
916	\end{tabular}\\[2pt]
917	{\footnotesize All verifiers fine-tuned on MultiNLI. Unknown recall ${<}3.5\%$ across all verifiers.}
918	\end{table}
919	
920	\paragraph{Three-verifier BH correction.}
921	\label{app:3verifier-bh}
922	Table~\ref{tab:3verifier-bh} applies Benjamini--Hochberg correction across all 15 Mistral-7B verifier--weight conditions ($m{=}15$, $\alpha{=}0.05$; distinct from the $m{=}12$ cross-generator analysis in \S\ref{sec:cross-arch}). Ten of 15 conditions remain significant after correction, confirming that multi-verifier NLI gains are robust to multiple testing.
923	
924	\begin{table}[h]
925	\centering
926	\small
927	\caption{BH correction across 3 verifiers $\times$ 5 weights on Mistral-7B ProofWriter ($n{=}600$, $m{=}15$). \checkmark: $p_{\text{BH}} < 0.05$.}
928	\label{tab:3verifier-bh}
929	\setlength{\tabcolsep}{4pt}
930	\begin{tabular}{@{}lcccccc@{}}
931	\toprule
932	Verifier & $w{=}1$ & $w{=}2$ & $w{=}3$ & $w{=}4$ & $w{=}5$ \\
933	\midrule
934	DeBERTa-MNLI & & \checkmark & \checkmark & \checkmark & \checkmark \\
935	RoBERTa-MNLI & & & \checkmark & \checkmark & \checkmark \\
936	BART-MNLI & & & \checkmark & \checkmark & \checkmark \\
937	\bottomrule
938	\end{tabular}\\[2pt]
939	{\footnotesize 10/15 significant at $\alpha{=}0.05$ after BH correction. All $w{=}1$ conditions and RoBERTa $w{=}2$ are non-significant.}
940	\end{table}
941	
942	\section{Capability Gap Data Points}
943	\label{app:capability-gap}
944	
945	\begin{figure}[t]
946	\centering
947	\includegraphics[width=0.78\columnwidth]{figures/capability_gap_scatter}
948	\caption{Combo gain vs.\ capability gap (verifier standalone $-$ generator SC) at $w{=}3$ across three NLI architectures. Gain decreases monotonically (Spearman $\rho = 1.0$, exact permutation $p = 0.003$, $n{=}6$; four of six conditions share the DeBERTa verifier---see Limitations); significant gains occur only for generators below the verifier's standalone accuracy. Stars: domain-adapted DeBERTa (99.67\% standalone, Table~\ref{tab:finetuned-nli}).}
949	\label{fig:capability-gap}
950	\end{figure}
951	
952	Table~\ref{tab:cross_generator_nli} reports the controlled cross-generator comparison with DeBERTa-large-mnli on ProofWriter ($n{=}600$). We extend this analysis by pairing Mistral-7B with two additional NLI architectures: BART-large-mnli (46.17\% standalone, combo $+5.17$\,pp, $p = 0.0002$) and RoBERTa-large-mnli (37.67\% standalone, combo $+4.17$\,pp, $p = 0.003$). All three NLI architectures produce significant gains on Mistral-7B at $w \geq 3$.
953	
954	Across all six ProofWriter verifier-generator pairs at $w{=}3$ (three verifiers $\times$ Mistral-7B plus three negative-gap generators $\times$ DeBERTa), combo gain decreases monotonically with the capability gap (Spearman $\rho = 1.0$, exact permutation $p = 0.003$, $n = 6$; however, four of six conditions share the DeBERTa verifier, which may reduce effective degrees of freedom---see Limitations; Figure~\ref{fig:capability-gap}). Significant $w{=}3$ gains are observed only for Mistral-7B (SC 39.33\%, below the verifier); the three above-verifier generators show no significant improvement at any $w$. After BH correction ($m{=}12$), two of twelve conditions survive: Mistral-7B $w{=}3$ (adj.\ $p = 6.78 \times 10^{-5}$) and $w{=}5$ (adj.\ $p = 7.41 \times 10^{-6}$).
955	
956	\paragraph{Robustness check.} Including all nine conditions (three verifiers $\times$ three weight levels on Mistral-7B) yields Spearman $\rho = 0.836$ (exact permutation $p = 0.007$, $n = 9$), confirming that the monotonic trend is robust to the choice of weight parameter.
957	
958	\paragraph{Full NLI combo with BH correction.}
959	\label{app:nli-combo-full}
960	
961	\begin{table}[h]
962	\centering
963	\small
964	\caption{Full cross-generator NLI combo results on ProofWriter depth-5 ($n{=}600$) with Benjamini--Hochberg correction ($m{=}12$, $\alpha{=}0.05$). All conditions use DeBERTa-large-mnli verifier (55.00\% standalone). Two of twelve conditions survive correction (Mistral-7B $w{=}3$ and $w{=}5$). {***}\,$p_{\text{BH}} < 0.001$.}
965	\label{tab:nli-combo-full}
966	\setlength{\tabcolsep}{3.5pt}
967	\resizebox{\columnwidth}{!}{%
968	\begin{tabular}{@{}llrrrrl@{}}
969	\toprule
970	Generator & $w$ & Combo (\%) & $\Delta$ (pp) & $p_{\text{raw}}$ & $p_{\text{BH}}$ & \\
971	\midrule
972	\multirow{3}{*}{\shortstack[l]{Mistral-7B\\{\scriptsize SC\,39.33\%, gap\,$+$15.67}}}
973	  & 1 & 40.17 & $+$0.83 & .359 & .721 & \\
974	  & 3 & 46.00 & $+$6.67 & $1.13{\times}10^{-5}$ & $6.78{\times}10^{-5}$ & {***} \\
975	  & 5 & 50.33 & $+$11.00 & $6.18{\times}10^{-7}$ & $7.41{\times}10^{-6}$ & {***} \\
976	\addlinespace
977	\multirow{3}{*}{\shortstack[l]{LLaMA-3.1-8B\\{\scriptsize SC\,72.50\%, gap\,$-$17.50}}}
978	  & 1 & 73.33 & $+$0.83 & .359 & .721 & \\
979	  & 3 & 73.33 & $+$0.83 & .665 & .886 & \\
980	  & 5 & 72.00 & $-$0.50 & .871 & 1.000 & \\
981	\addlinespace
982	\multirow{3}{*}{\shortstack[l]{Qwen2.5-14B\\{\scriptsize SC\,74.00\%, gap\,$-$19.00}}}
983	  & 1 & 74.17 & $+$0.17 & 1.000 & 1.000 & \\
984	  & 3 & 74.67 & $+$0.67 & .503 & .755 & \\
985	  & 5 & 75.17 & $+$1.17 & .360 & .721 & \\
986	\addlinespace
987	\multirow{3}{*}{\shortstack[l]{Qwen3-14B\\{\scriptsize SC\,85.83\%, gap\,$-$30.83}}}
988	  & 1 & 86.00 & $+$0.17 & 1.000 & 1.000 & \\
989	  & 3 & 86.33 & $+$0.50 & .453 & .755 & \\
990	  & 5 & 87.00 & $+$1.17 & .210 & .721 & \\
991	\bottomrule
992	\end{tabular}}
993	\end{table}
994	
995	\paragraph{BART-large-mnli cross-generator results.}
996	
997	\begin{table}[h]
998	\centering
999	\small
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c6f24b29-6aae-47b7-b656-8e88955ff4e7",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "255d63ae-11f6-41b5-864b-6ac8e2fc9443",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
      "content": "\\addlinespace\n24 & Atom pipeline & Paradigm & Decomposition & $-$10.0 & Atomic extraction degrades \\\\\n25 & Premise-only filter & Constraint sel.\\ & Bias isolation & $+$2.45 & $p = 0.359$; halves conclusion-bias \\\\\n26 & DPP trace selection & Trace diversity & Determinantal & $+$1.47 & $p = 0.629$; $K_{\\text{sel}}{=}8$ \\\\\n27 & Z3 strict-mode & Solver config & UNSAT filtering & 0.0 & McNemar $b{=}1, c{=}1$; 63\\% UNSAT \\\\\n\\bottomrule\n\\end{tabular}\\\\[2pt]\n{\\footnotesize All experiments on Mistral-7B FOLIO ($n{=}204$) unless noted. $^\\dagger$\\,Oscillates without convergence; net effect $\\approx 0$. $^*$\\,Accuracy gain only at reduced coverage (diagnostic value, not a general improvement). Methods 1--12 are reported in Table~\\ref{tab:remediation} and Table~\\ref{tab:method_interventions}.}\n\\end{table*}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig3_process_kappa_scatter.pdf}\n\\caption{Answer agreement vs.\\ CoT cosine similarity (Mistral-7B, FOLIO, $n{=}204$). Flat regression ($r = -0.06$, $p = 0.36$); stronger models show significant positive correlation ($r = +0.24$, Qwen-14B; Table~\\ref{tab:cross-model-process}).}\n\\label{fig:process-kappa}\n\\end{figure}\n\n\n\\section{Extraction Error Taxonomy}\n\\label{app:extraction}\n\\label{sec:extraction-taxonomy}\n\nConstraints must discriminate between candidate answers for MAX-SAT to produce a ranking different from majority vote. We measure discriminative power at two levels on Qwen2.5-14B across FOLIO and ProofWriter ($n = 804$). At the source-trace level, 39.2\\% of total constraint weight originates from traces whose answer differs from the plurality, but only 12.1\\% of individual constraints fall into this minority category. At the Z3 semantic level, 91.8\\% of constraints [95\\% CI: 91.2, 92.4] are technically discriminative, producing different satisfiability outcomes when evaluated against different candidate answers. Only 8.2\\% are non-discriminative.\n\nThe high discriminative rate does not translate into accuracy gains because discrimination mirrors the model's own answer distribution. Each trace produces constraints with its own variable names, so Z3 treats identically-intended propositions as unrelated symbols; among cross-answer constraint pairs, 56.4\\% share zero Z3 variables. This variable isolation means constraints from different traces are trivially jointly satisfiable, and MAX-SAT retains nearly all of them regardless of source answer. Removing the 8.2\\% non-discriminative constraints yields zero accuracy improvement. The discriminative majority does not provide independent signal; it reinforces the majority answer that SC would already select. This confirmation bias, not a lack of discrimination, explains why SICA degenerates to majority voting (Appendix~\\ref{app:ablation}).\n\n\n\\section{Hyperparameter Sensitivity}\n\\label{app:sensitivity}\n\\label{sec:k-sensitivity}\n\\label{sec:t-sensitivity}\n\n\\subsection{K Sensitivity}\n\nFigure~\\ref{fig:k-sensitivity} shows SICA $\\Delta$ as a function of the number of sampled traces $K$ for Mistral-7B on FOLIO ($n = 204$, no fixed seed). The relationship is non-monotonic: $K = 4$ yields $\\Delta = -1.47$\\,pp, $K = 8$ yields $\\Delta = -1.96$\\,pp, $K = 12$ reaches $\\Delta = +3.43$\\,pp, $K = 16$ drops to $\\Delta = +1.47$\\,pp, and $K = 20$ partially recovers to $\\Delta = +1.96$\\,pp. The recovery at $K = 20$ rules out a simple peaked pattern, but $K = 12$ remains the only setting with $\\Delta > 2$\\,pp ($p = 0.092$, marginal).\n\nThe apparent $\\Delta$ peak at $K = 12$ is confounded with SC baseline. SICA absolute accuracy plateaus at 59.31\\% (121/204) for $K \\geq 12$: identical at $K = 12$ and $K = 20$. The $\\Delta$ variation across these settings is driven primarily by SC fluctuations rather than by SICA improvement. $K = 12$ produces a relatively low SC (55.88\\%), placing it in the intermediate-SC region; $K = 8$ (SC $= 58.33\\%$) and $K = 20$ (SC $= 57.35\\%$) have higher baselines, compressing $\\Delta$ even though SICA accuracy does not change for $K \\geq 12$. Additional traces beyond $K = 12$ provide no benefit to SICA absolute performance, consistent with the constraint quality bottleneck. The $K = 12$ $\\Delta$ captures only 25.0\\% of the oracle ceiling ($+13.73$\\,pp).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{f3_k_sensitivity}\n\\caption{SICA $\\Delta$ (pp) vs.\\ number of traces $K$ for Mistral-7B on FOLIO ($n = 204$, default seed, $T = 0.7$). Non-monotonic pattern: SICA accuracy plateaus at 59.31\\% for $K \\geq 12$; the apparent $\\Delta$ peak at $K = 12$ partly reflects a relatively low SC baseline (55.88\\%) at that point. Error bars: 95\\% bootstrap CI.}\n\\label{fig:k-sensitivity}\n\\end{figure}\n\n\\subsection{Temperature Sensitivity}\n\nTemperature sensitivity on Mistral-7B FOLIO ($n = 204$, default seed) reveals a sharp isolated peak rather than a smooth trend. Across four temperature settings, only $T = 0.7$ produces a positive effect: $T = 0.3$ yields $\\Delta = -1.47$\\,pp (SC $= 58.33\\%$), $T = 0.5$ yields $\\Delta = -0.98$\\,pp (SC $= 58.33\\%$), $T = 0.7$ yields $\\Delta = +3.43$\\,pp (SC $= 55.88\\%$), and $T = 1.0$ yields $\\Delta = 0.00$\\,pp (SC $= 55.39\\%$). All other temperatures yield negative or null effects, and the single positive result at $T = 0.7$ is confounded with SC baseline. Combined with the seed sensitivity (0 of 4 seeds reaching $p < 0.05$ at $T = 0.7$), the positive trend depends on a specific combination of temperature, seed, and baseline accuracy that same-model sampling rarely achieves.\n\nThe parallel between $K$ and $T$ sensitivity points to a common underlying variable. In both sweeps, the setting that produces the largest SICA gain also produces a relatively low SC baseline (55.88\\%), which places it in the intermediate-SC region. The hyperparameters themselves ($K$, $T$) are not the causal driver; they modulate SC level, and it is the SC level that determines whether SICA has operating room.\n\n\n\\section{Entropy Decomposition}\n\\label{app:entropy}\n\\label{sec:entropy}\n\nWe partition problems by trace agreement: high-entropy (majority count $\\leq 8$ out of $K = 12$) and low-entropy (majority count $\\geq 9$). Table~\\ref{tab:entropy} reports SICA $\\Delta$ within each partition across eight model-dataset conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Entropy decomposition of SICA $\\Delta$ (pp). High-entropy: majority count $\\leq 8$; low-entropy: majority count $\\geq 9$. $^\\dagger$Partial data (180/600). Pre-tiebreaking SC values; pattern robust to D064 correction.}\n\\label{tab:entropy}\n\\begin{tabular}{@{}llrrrr@{}}\n\\toprule\nModel & Dataset & \\multicolumn{2}{c}{High-entropy} & \\multicolumn{2}{c}{Low-entropy} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){5-6}\n & & $n$ & $\\Delta$ & $n$ & $\\Delta$ \\\\\n\\midrule\nMistral-7B & FOLIO & 78 & $\\mathbf{+12.8}$ & 126 & 0.0 \\\\\nMistral-7B (s123) & FOLIO & 77 & $\\mathbf{+9.1}$ & 127 & 0.0 \\\\\nMistral-7B (s456) & FOLIO & 75 & $-$1.3 & 129 & 0.0 \\\\\nMistral-7B & PW-D5 & 267 & $-$4.9 & 333 & $-$1.2 \\\\\nQwen2.5-14B & FOLIO & 37 & $-$8.2 & 167 & $-$0.6 \\\\\nQwen2.5-14B & LogiQA & 23 & $-$4.3 & 177 & 0.0 \\\\\nQwen2.5-7B & FOLIO & 47 & $-$2.1 & 157 & 0.0 \\\\\nLLaMA-3.1-8B$^\\dagger$ & PW-D5 & 76 & $-$3.9 & 104 & $-$1.9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTwo patterns emerge. First, low-entropy problems produce $\\Delta \\approx 0$\\,pp across all eight conditions: when traces agree, constraints carry no information beyond the majority vote.\n\nSecond, the direction of SICA's effect on high-entropy problems depends on the accuracy regime, not on entropy alone. In the intermediate-SC region (Mistral-7B on FOLIO, default-seed and seed-123 runs), high-entropy $\\Delta$ reaches $+12.8$ and $+9.1$\\,pp: traces genuinely disagree, and constraints from correct-answer traces provide discriminative signal that resolves the disagreement. In Type~A conditions (Qwen2.5-14B on FOLIO, $\\Delta = -8.2$\\,pp), high-entropy problems represent rare deviations from a strong model's consensus; constraints inherit the model's confirmation bias. In Type~C (Mistral-7B on ProofWriter, $\\Delta = -4.9$\\,pp), high-entropy problems reflect systematic errors. The mechanism is not entropy per se but the interaction of entropy with model capability.\n\n\n\\section{Failure Mode Analysis}\n\\label{app:failure-modes}\n\\label{sec:failure-modes}\n\nThe regime-dependent pattern in Table~\\ref{tab:main_results} reflects three distinct failure modes of self-extracted logical constraints.\n\n\\paragraph{Type A: confirmation bias (SC $\\geq$ $\\sim$60\\%).} Strong models produce consistent reasoning traces, and constraints extracted from those traces mirror the answer distribution. When most constraints support the same candidate, MAX-SAT excludes few clauses ($|\\mathcal{C}^{\\setminus}| \\approx 0$), the penalty term in Eq.~\\ref{eq:score} vanishes, and the scoring function degenerates to weighted vote counting (Eq.~\\ref{eq:degenerate}). SICA and SC then produce identical predictions. The ablation in Appendix~\\ref{app:ablation} confirms this empirically: on Qwen2.5-14B (FOLIO + ProofWriter, $n = 804$), MAX-SAT and count-only baselines agree on 803 of 804 predictions.\n\n\\paragraph{Type B: non-formalizable domains.} LogiQA problems require pragmatic and contextual reasoning that resists clean logical formalization. Qwen2.5-14B on LogiQA achieves an extraction rate of 86.4\\%, but the resulting constraints have a contradiction rate of only 0.8\\%: extracted formulas rarely conflict across traces, leaving MAX-SAT with no logical tension to exploit. Mistral-7B on LogiQA sits in the same SC range (50.00\\%) yet produces $\\Delta = +1.50$\\,pp ($p = 0.581$); Qwen2.5-14B on the same domain yields $\\Delta = -1.00$\\,pp ($p = 0.625$). Neither model benefits, confirming that the right accuracy regime is necessary but not sufficient when the domain resists formalization.\n\n\\paragraph{Type C: error amplification (SC $\\leq$ $\\sim$40\\%).} When model accuracy is low, the majority of traces reach incorrect answers. Constraints extracted from wrong traces encode incorrect reasoning as formal rules. Z3 treats these rules as soft clauses with weight proportional to their frequency, so the solver preferentially satisfies the wrong constraints and penalizes traces that happen to reach the correct answer. Mistral-7B on ProofWriter ($\\Delta = -2.83$\\,pp, raw $p = 0.014$; BH adj.\\ $p = 0.066$) demonstrates this effect: SICA converts a weak positive signal in trace diversity into a net negative by formalizing the errors.\n\n\n\\section{Cross-Model Confirmation Bias}\n\\label{app:cross-model-bias}\n\nTable~\\ref{tab:cross-model-bias} reports MaxSAT-weighted confirmation bias metrics across three model families on FOLIO ($n = 204$). Weighted bias ratio and wrong-supporting constraint percentage both decrease with model capability, while SICA's accuracy effect shifts from positive (Mistral, intermediate-SC regime) to negative (LLaMA, high-SC regime). Raw bias ratios ($4.97\\times$, $3.85\\times$, $2.88\\times$) are reported in \\S\\ref{sec:confirmation-bias}. LLaMA weighted BR CI: [2.19, 3.28].\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-model confirmation bias on FOLIO ($n = 204$, $K = 12$). BR (wtd.): MaxSAT-weighted ratio of error-supporting constraints on incorrect vs.\\ correct problems. Wrong \\%: weighted fraction of constraints supporting the incorrect majority on error problems. $\\Delta$: SICA $-$ SC (pp).}\n\\label{tab:cross-model-bias}\n\\begin{tabular}{@{}lrrr@{}}\n\\toprule\nModel & BR (wtd.) & Wrong (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\nMistral-7B & $4.24\\times$ & 80.9 & $+$4.90 \\\\\nQwen2.5-14B & $3.69\\times$ & 78.7 & $-$0.98 \\\\\nLLaMA-3.1-8B & $2.66\\times$ & 72.7 & $-$4.41 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Frontier model universality.}\n\\label{app:frontier-scb}\nTable~\\ref{tab:frontier-scb} (main text, \\S\\ref{sec:confirmation-bias}) extends confirmation bias analysis to nine models spanning 7B open-source to frontier closed-source. All models exhibit $\\text{BR} > 1$ (range: $1.66$--$4.97\\times$). Extraction context varies: open-source models use self-extraction (the model extracts constraints from its own traces); frontier models use cross-model extraction (Mistral-7B extracts FOL from the target model's traces), as closed-source APIs do not expose internal representations suitable for direct symbolic extraction.\n\n\\paragraph{ProcessSim definition.}\n\\label{app:process-sim}\nProcess similarity is the mean pairwise cosine similarity of TF-IDF trace representations:\n\\begin{equation}\n\\label{eq:process-sim}\n\\text{ProcessSim}(q) = \\frac{2}{K(K{-}1)} \\sum_{i < j} \\cos(\\mathbf{v}_i^q, \\mathbf{v}_j^q),\n\\end{equation}\nwhere $\\mathbf{v}_i^q$ is the TF-IDF vector of trace $t_i$ for question $q$.\n\n\\paragraph{Process-$\\kappa$ gradient.}\n\\label{app:process-gradient}\nUnder cross-model extraction (Mistral-7B extracts FOL from other models' traces), SICA gain decreases monotonically with process-level cosine similarity (Table~\\ref{tab:process-gradient}; Spearman $\\rho = -1.0$, $n = 5$, one-tailed $p = 0.0083$). Gain requires two conditions: diverse traces (low $\\kappa_{\\text{proc}}$) \\emph{and} substantial self-bias (high BR). R1-Distill-8B satisfies both ($\\kappa_{\\text{proc}} = 0.248$, $\\text{BR} = 2.92$) and gains $+2.45$\\,pp; o3 has moderate trace diversity ($\\kappa_{\\text{proc}} = 0.596$) but near-minimal bias ($\\text{BR} = 1.66$, exhibiting a bimodal error pattern: 82\\% of error problems have $\\text{BR} = \\infty$ but low finite-BR), yielding $\\Delta = 0$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Process-$\\kappa$ gradient under cross-model extraction (Mistral-7B $\\rightarrow$ target model traces, FOLIO). $\\kappa_{\\text{proc}}$: process-level cosine similarity. $\\Delta$: SICA $-$ SC (pp). Spearman $\\rho(\\kappa_{\\text{proc}} \\rightarrow \\Delta) = -1.0$, $p = 0.0083$. $^*$Interim ($n = 95/204$).}\n\\label{tab:process-gradient}\n\\begin{tabular}{@{}lrrr@{}}\n\\toprule\nModel & $\\kappa_{\\text{proc}}$ & $\\Delta$ (pp) & BR \\\\\n\\midrule\nR1-Distill-8B & 0.248 & $+$2.45 & 2.92 \\\\\ngpt-5.5 & 0.563 & $+$0.49 & 3.48 \\\\\no3 & 0.596 & 0.00 & 1.66 \\\\\nGemini-2.5-Pro$^*$ & 0.790 & $-$1.05 & 2.79 \\\\\ngpt-4.1 & 0.792 & $-$1.47 & 2.70 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Independence-Accuracy Scatter Plot}\n\\label{app:kappa-scatter}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/f6_kappa_accuracy_scatter}\n\\caption{Independence-accuracy trade-off across aggregation methods (Mistral-7B, filled markers) and model families (LLaMA-3.1-8B, Qwen2.5-7B, Qwen2.5-14B; open markers) on FOLIO ($n = 204$). Same-model methods cluster at $\\kappa \\approx 0.40$--$0.47$ (gray band), while cross-model SC shows stronger correlations ($\\kappa = 0.41$--$0.74$) at higher accuracy. Debate breaks correlation ($\\kappa = 0.15$) at catastrophic accuracy cost. Dashed line: Mistral-7B SC baseline.}\n\\label{fig:kappa-accuracy}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Independence-accuracy trade-off (FOLIO, $n = 204$). Top: aggregation methods on Mistral-7B; bottom: SC across three model families. All families produce $\\kappa \\geq 0.41$, confirming an architecture-independent ceiling. $\\kappa$: Fleiss' kappa on raw answers.}\n\\label{tab:kappa_generalization}\n\\setlength{\\tabcolsep}{3.5pt}\n\\begin{tabular}{@{}llccrr@{}}\n\\toprule\nModel & Aggregation & $\\kappa$ & Eff-$K$ & $K$ & Acc.\\ (\\%) \\\\\n\\midrule\nMistral-7B & Debate & 0.15 & 4.44 & 12 & 38.24 \\\\\n& Diverse-Prompt & 0.40 & 2.21 & 12 & 54.41 \\\\\n& Self-Consistency & 0.44 & 2.02 & 10 & 56.86 \\\\\n& ICG & 0.47 & 1.93 & 10 & 51.96 \\\\\n\\addlinespace\nLLaMA-3.1-8B & Self-Consistency & 0.41 & 2.17 & 12 & 66.18 \\\\\nQwen2.5-7B & Self-Consistency & 0.66 & 1.46 & 12 & 75.98 \\\\\nQwen2.5-14B & Self-Consistency & 0.74 & 1.32 & 12 & 75.98 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Trace independence metrics.}\n\\label{app:trace-independence}\n\nTable~\\ref{tab:independence} reports the full 15-condition breakdown of Fleiss' $\\kappa$ and Effective-K at $K = 12$, referenced in \\S\\ref{sec:effective-k}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\caption{Trace independence metrics ($K = 12$, sorted by $\\kappa$ descending). $\\kappa$: Fleiss' Kappa. $K_{\\text{eff}}$: Effective-K (Eq.~\\ref{eq:effk}). SC: Self-Consistency baseline. $\\Delta$: SICA $-$ SC (pp). {*}\\,$p < 0.05$ (uncorrected; BH adj.\\ $p = 0.066$, $m{=}6$); positive $\\Delta$ values do not reach significance. multi-T $= T \\in \\{0.3, 0.7, 1.2\\}$, 4 traces each.}\n\\label{tab:independence}\n\\begin{tabular}{@{}llccrr@{}}\n\\toprule\nModel & Condition & $\\kappa$ & $K_{\\text{eff}}$ & SC (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\nQwen3 (think) & FOLIO & 0.91 & 1.09 & 86.27 & $+$0.49 \\\\\nQwen2.5-14B & LogiQA & 0.82 & 1.20 & 79.00 & $-$1.00 \\\\\nQwen3 & FOLIO & 0.77 & 1.26 & 83.33 & $+$1.47 \\\\\nQwen2.5-14B & FOLIO & 0.74 & 1.30 & 75.98 & $-$0.49 \\\\\nQwen2.5-7B & FOLIO & 0.66 & 1.46 & 75.98 & $+$0.49 \\\\\n\\addlinespace\nMistral-7B ($T{=}0.3$) & FOLIO & 0.53 & 1.77 & 58.33 & $-$1.47 \\\\\nMistral-7B & LogiQA & 0.51 & 1.81 & 50.00 & $+$1.50 \\\\\nMistral-7B (s456) & FOLIO & 0.51 & 1.82 & 55.88 & 0.00 \\\\\nMistral-7B & FOLIO & 0.50 & 1.84 & 55.88 & $+$3.43 \\\\\nMistral-7B (s123) & FOLIO & 0.49 & 1.88 & 54.41 & $+$2.94 \\\\\nMistral-7B (s789) & FOLIO & 0.45 & 2.03 & 59.31 & $-$2.45 \\\\\nMistral-7B ($T{=}0.5$) & FOLIO & 0.52 & 1.80 & 58.33 & $-$0.98 \\\\\nMistral-7B (multi-T) & FOLIO & 0.48 & 1.91 & 57.84 & 0.00 \\\\\nMistral-7B ($T{=}1.0$) & FOLIO & 0.48 & 1.91 & 55.39 & 0.00 \\\\\nMistral-7B & PW-D5 & 0.21 & 3.62 & 39.33 & $\\mathbf{-2.83}${*} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Cross-Model Kappa Analysis}\n\\label{app:cross-model-kappa}\n\nTable~\\ref{tab:cross_model_kappa} compares trace independence across three model families on the same benchmarks. On FOLIO ($n = 204$), all four models produce $\\kappa \\geq 0.41$: LLaMA-3.1-8B ($\\kappa = 0.41$), Mistral-7B ($\\kappa = 0.44$), Qwen2.5-7B ($\\kappa = 0.66$), and Qwen2.5-14B ($\\kappa = 0.74$). The bottleneck is architecture-independent---no family escapes the correlation floor. Within the Qwen family, $\\kappa$ increases from 0.66 (7B) to 0.74 (14B), but Mistral-7B (7B) and LLaMA-3.1-8B (8B) differ by $\\Delta\\kappa = 0.03$ despite belonging to different families, suggesting that cross-family variation ($\\Delta\\kappa$ up to 0.22 at similar scale) exceeds within-family scale effects ($\\Delta\\kappa = 0.08$). Disentangling scale from architecture requires controlled same-family experiments across $\\geq$3 scales.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-model trace independence ($K = 12$, SC aggregation, FOLIO + ProofWriter). Higher $\\kappa$ indicates stronger correlation and lower effective sample size.}\n\\label{tab:cross_model_kappa}\n\\begin{tabular}{@{}llccr@{}}\n\\toprule\nModel & Dataset & $\\kappa$ & $K_{\\text{eff}}$ & SC (\\%) \\\\\n\\midrule\nQwen2.5-14B & FOLIO & 0.74 & 1.32 & 75.98 \\\\\nQwen2.5-7B & FOLIO & 0.66 & 1.46 & 75.98 \\\\\nMistral-7B & FOLIO & 0.44 & 2.02 & 56.86 \\\\\nLLaMA-3.1-8B & FOLIO & 0.41 & 2.17 & 66.18 \\\\\n\\addlinespace\nQwen2.5-14B & PW-D5 & 0.62 & 1.54 & --- \\\\\nMistral-7B & PW-D5 & 0.21 & 3.62 & 39.33 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Cross-Model Process-Level Independence}\n\\label{app:cross-model-process}\n\nTable~\\ref{tab:cross-model-process} extends the process-level independence analysis (\\S\\ref{sec:process-kappa}) to four model families on FOLIO ($n = 204$). Mean pairwise cosine similarity of TF-IDF trace representations exceeds answer-level $\\kappa$ in every family, but the gap is model-strength dependent: it narrows from $0.31$ (LLaMA) and $0.23$ (Mistral) to $0.02$ (Qwen-14B). For weaker models ($r \\approx 0$), answer diversity does not reflect reasoning diversity---process-convergent but answer-divergent trace pairs constitute 9.5\\% of all pairs on Mistral-7B versus 2.5--3.2\\% on other families. For stronger models ($r \\approx 0.23$, $p \\leq 0.001$), process and answer agreement align, and answer-level $\\kappa$ already captures the bottleneck. Process-$\\kappa$ thus provides a crucial additional diagnostic specifically for weaker models, where answer-level metrics underestimate reasoning homogeneity.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-model process-level independence on FOLIO ($n = 204$, $K = 12$). Mean Cosine: mean pairwise TF-IDF cosine similarity of reasoning traces (Eq.~\\ref{eq:process-sim}). Answer $\\kappa$: per-question answer agreement. Gap: Cosine $-$ $\\kappa$. $r$: Pearson correlation between ProcessSim and answer agreement. Conv.: fraction of process-convergent but answer-divergent trace pairs. {*}{*}\\,$p < 0.01$; {*}{*}{*}\\,$p < 0.001$.}\n\\label{tab:cross-model-process}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccrlr@{}}\n\\toprule\nModel & Mean Cos. & Ans.\\ $\\kappa$ & Gap & $r$ & $p$ & Conv.\\ (\\%) \\\\\n\\midrule\nMistral-7B & 0.690 & 0.460 & 0.230 & $-$0.064 & 0.362 & 9.5 \\\\\nLLaMA-3.1-8B & 0.759 & 0.447 & 0.312 & $-$0.001 & 0.985 & 3.2 \\\\\nQwen2.5-7B & 0.790 & 0.658 & 0.132 & $+$0.226 & 0.001{*}{*} & 2.8 \\\\\nQwen2.5-14B & 0.766 & 0.744 & 0.022 & $+$0.244 & ${<}$0.001{*}{*}{*} & 2.5 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Representation robustness.} Replacing TF-IDF with SBERT embeddings (all-MiniLM-L6-v2) yields ProcessSim $= 0.91$ (vs.\\ TF-IDF $0.74$), widening the gap over answer-level $\\kappa = 0.55$. The process homogeneity finding is robust to representation choice.\n\n\\section{Constraint Quality Across Methods}\n\\label{app:constraint-quality}\n\nTable~\\ref{tab:constraint_quality} compares constraint quality metrics across the three method-level interventions on Mistral-7B FOLIO ($n = 204$). Standard SICA extracts from reasoning traces and achieves the highest parse rate (97.1\\%) but also the highest redundancy (42.9\\%): nearly half of all constraints are syntactic duplicates across the 12 traces, quantifying the co-sourcing effect of same-model generation. ICG generates constraints directly from the problem statement without trace conditioning. Its lower parse rate (74.6\\%) reflects the difficulty of standalone formalization at the 7B scale, though successfully parsed constraints compile at a higher rate (99.4\\% vs.\\ 96.5\\%). ICG produces fewer unique constraints per question (24.9 vs.\\ 39.3) with lower redundancy (32.3\\%), consistent with the absence of trace-level repetition. Contrastive scoring generates pro and con constraint sets for each candidate answer. The format yields far fewer unique constraints per question (9.2) with zero redundancy (each pro/con pair is structurally distinct), but 62.7\\% of constraints are trivially satisfied by Z3---they impose no logical tension and cannot discriminate between candidates. Only 51.0\\% of Contrastive constraints are discriminative, compared to 81.4\\% for standard SICA and 77.0\\% for ICG.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Constraint quality metrics across method-level interventions (Mistral-7B, FOLIO, $n = 204$). Parse: fraction of extraction attempts yielding valid JSON. Z3 Compile: fraction compiling to Z3 formulas. Unique/q: mean unique constraints per question. Redundancy: fraction of constraints duplicated across traces. Disc.: fraction discriminative (different Z3 outcome per candidate). Triv.\\ Sat.: fraction trivially satisfied (no logical tension).}\n\\label{tab:constraint_quality}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}l rrrrrr@{}}\n\\toprule\nMethod & Parse & Z3 & Uniq/q & Redund. & Disc. & Triv.\\ Sat. \\\\\n\\midrule\nStandard SICA & 97.1\\% & 96.5\\% & 39.3 & 42.9\\% & 81.4\\% & --- \\\\\nICG & 74.6\\% & 99.4\\% & 24.9 & 32.3\\% & 77.0\\% & --- \\\\\nContrastive & 74.0\\% & 94.4\\% & 9.2 & 0.0\\% & 51.0\\% & 62.7\\% \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Per-trace constraint yield uniformity.}\n\\label{app:yield-cv}\n\nObservation~1 assumes approximately uniform constraint yield per trace within each answer group. We verify this on Mistral-7B FOLIO ($K{=}12$, $n{=}204$). Per-problem yield CV (coefficient of variation across traces within each problem) has median $0.257$ and mean $0.319$; 64.2\\% of problems fall below $\\text{CV} = 0.3$, and 91.2\\% below $0.5$, supporting the uniformity assumption. Majority-answer traces average $5.61$ constraints and minority-answer traces $6.04$ (Mann--Whitney $p = 5.2 \\times 10^{-6}$); correct-answer traces average $5.41$ and incorrect $6.05$ ($p = 5.3 \\times 10^{-11}$). Although statistically significant, the absolute difference (${\\sim}0.6$ constraints, $< 12\\%$) is insufficient to alter the argmax-preservation result: SICA and SC select the same answer on ${>}96\\%$ of problems regardless of yield variation.\n\n\\section{Error Categorization of Method-Level Interventions}\n\\label{app:error-categorization}\n\nWe categorize discordant predictions (where the method and SC disagree) for Debate and Contrastive on FOLIO ($n = 204$) to understand why these interventions degrade accuracy.\n\n\\paragraph{Debate discordant analysis.} Debate produces 60 correct$\\to$wrong flips and 22 wrong$\\to$correct flips on FOLIO. Answer-type breakdown reveals that False-labeled questions are most vulnerable: 82.8\\% of False questions that SC answers correctly are flipped by Debate, compared to 63.9\\% for True and 25.5\\% for Unknown. Counterintuitively, failures concentrate not where debate breaks down but where it succeeds most thoroughly: discordant questions average 2.93 effective debate rounds (proposer-critic exchanges producing substantive updates) versus 2.52 for concordant ones. More extensive same-model debate produces more confident but incorrect constraints, consistent with the independence limitation---the critic draws on the same model distribution as the proposer, reinforcing shared biases rather than correcting them.\n\n\\paragraph{Contrastive discordant analysis.} Contrastive produces 34 discordant questions on FOLIO. All 34 produced non-degenerate scores (both pro and con constraint sets non-empty), compared to 20.1\\% degenerate scores in the full sample. This indicates that scoring failures on discordant questions stem from systematic pro-bias rather than missing constraints. Among discordant questions, 97.1\\% contain negation words in the problem statement versus 76.5\\% in the full sample, suggesting that negation-bearing problems are particularly susceptible to pro-constraint imbalance. The average pro/con score ratio is 1.0 for discordant questions versus 0.68 for the full sample: the method generates balanced-looking scores that mask directional errors.\n\n\\paragraph{Cross-method overlap.} Of the 79 unique questions on which either method disagrees with SC, only 15 overlap between Debate and Contrastive (Jaccard index $= 0.19$). All 15 shared discordant questions contain negation words. The low overlap confirms that the two methods attack different vulnerability types---Debate through extended same-model argumentation that amplifies confident errors, Contrastive through pro-bias in constraint generation---while sharing a common root cause in correlated same-model voting: both methods rely on the same model's output distribution and cannot introduce genuinely independent signal.\n\n\n\\section{TOST Equivalence Tests}\n\\label{app:tost}\n\nWe apply two one-sided tests (TOST) \\citep{lakens2017equivalence} with equivalence margin $\\pm 2$\\,pp to all 16 non-degenerate SICA--SC comparisons, classifying each condition as \\emph{equivalent} (TOST significant), \\emph{genuinely different} (McNemar $p < 0.05$ and TOST not significant), or \\emph{underpowered} (neither test significant). Four conditions are equivalent, confirming that SICA and SC produce statistically indistinguishable accuracy. Two conditions show genuine differences, both negative: Mistral-7B ProofWriter ($-2.83$\\,pp, $p = 0.014$) and Qwen2.5-14B ProofWriter ($-2.50$\\,pp, $p = 0.011$). The remaining ten conditions are underpowered, reflecting the limited statistical power at $n{=}200$--$204$ for detecting $|\\Delta| \\leq 2$\\,pp effects.\n\n\\paragraph{Margin sensitivity.} Table~\\ref{tab:tost-sensitivity} shows that the classification is robust across margins: regardless of the chosen margin, no condition shows a significant positive SICA effect.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{TOST classification sensitivity across equivalence margins (16 non-degenerate conditions).}\n\\label{tab:tost-sensitivity}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nMargin & Equivalent & Different & Underpowered \\\\\n\\midrule\n$\\pm 1$\\,pp & 0 & 2 & 14 \\\\\n$\\pm 2$\\,pp & 4 & 2 & 10 \\\\\n$\\pm 3$\\,pp & 10 & 0 & 6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Relative-margin TOST.}\n\\label{app:relative_tost}\nThe absolute $\\pm 2$\\,pp margin is more stringent at high baselines ($\\pm 2.4\\%$ relative at SC $= 85\\%$) than low ones ($\\pm 5.1\\%$ at SC $= 39\\%$). A relative $\\pm 5\\%$ of SC margin addresses this asymmetry: 8 conditions are equivalent, 2 genuinely different (both negative), and 6 underpowered. The additional four equivalent conditions are all high-SC ($\\geq 75\\%$), where the wider relative band captures practical indistinguishability. No condition shows a significant positive effect under either margin.\n\n\\paragraph{Conditional Correction Ratio data.}\n\\label{app:cil-data}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\caption{Conditional Correction Ratio across eight verifier--generator conditions. $\\text{CCR} > 0$: cross-arch NLI on ProofWriter. $\\text{CCR} < 0$: same-model SICA or weak capability gap.}\n\\label{tab:cil_main}\n\\begin{tabular}{@{}llrr@{}}\n\\toprule\nGenerator--Verifier & Dataset & CCR & $\\Delta$ (pp) \\\\\n\\midrule\nMistral $\\times$ BART-NLI & PW & $+$1.86 & $+$5.17 \\\\\nMistral $\\times$ DeBERTa-NLI & PW & $+$1.67 & $+$6.67 \\\\\nMistral $\\times$ RoBERTa-NLI & PW & $+$1.42 & $+$4.17 \\\\\n\\addlinespace\nQwen-14B $\\times$ DeBERTa-NLI & PW & $-$0.21 & $+$0.33 \\\\\nMistral $\\times$ DeBERTa-NLI & FOLIO & $-$0.47 & $+$2.94 \\\\\n\\addlinespace\nMistral $\\times$ SICA & FOLIO & $-$2.93 & $+$3.43 \\\\\nQwen-14B $\\times$ SICA & PW & $-$4.21 & $-$2.50 \\\\\nMistral $\\times$ SICA & PW & $-$4.61 & $-$2.83 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Disagreement-Routed Cascade details.}\n\\label{app:drc}\nDRC invokes NLI only when SC consensus falls below threshold $\\tau$, avoiding unnecessary verifier calls on high-agreement problems. Gains concentrate on weak generators (SC $< 40\\%$), consistent with the capability-gap hypothesis (\\S\\ref{sec:cross-arch}). Regime-dependent bottleneck analysis appears in Appendix~\\ref{app:2x2}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DRC on Mistral-7B ($K{=}12$, DeBERTa-large-mnli, $w{=}3$). $\\tau{=}0.7$ recovers 83--90\\% of full-combo gain at ${\\sim}35\\%$ NLI cost across both datasets.}\n\\label{tab:drc}\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\nDataset & Method & Acc.\\ & NLI Calls & Cost & Recovery \\\\\n\\midrule\n\\multirow{3}{*}{PW-D5} & SC only & 39.33\\% & 0/600 & 0\\% & --- \\\\\n& \\textbf{DRC $\\tau{=}0.7$} & \\textbf{45.33\\%} & \\textbf{207/600} & \\textbf{34.5\\%} & \\textbf{90.0\\%} \\\\\n& Full combo & 46.00\\% & 600/600 & 100\\% & 100\\% \\\\\n\\midrule\n\\multirow{3}{*}{FOLIO} & SC only & 55.88\\% & 0/204 & 0\\% & --- \\\\\n& \\textbf{DRC $\\tau{=}0.7$} & \\textbf{58.33\\%} & \\textbf{71/204} & \\textbf{34.8\\%} & \\textbf{83.3\\%} \\\\\n& Full combo & 58.82\\% & 204/204 & 100\\% & 100\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Multi-Verifier NLI Results}\n\\label{app:multi-nli}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-architecture NLI combo on ProofWriter depth-5 ($n{=}600$, Mistral-7B traces, SC $= 39.33\\%$). Three NLI verifiers $\\times$ three weight settings. {*}\\,$p < 0.05$;\\enspace{**}\\,$p < 0.01$;\\enspace{***}\\,$p < 0.001$ (McNemar).}\n\\label{tab:multi-nli}\n\\begin{tabular}{@{}llrrl@{}}\n\\toprule\nVerifier & Standalone & $w$ & $\\Delta$ (pp) & $p$ \\\\\n\\midrule\nDeBERTa-MNLI & 55.00\\% & 1 & $+$0.83 & n.s. \\\\\n & & 3 & $+$6.67 & ${<}0.001${***} \\\\\n & & 5 & $+$11.00 & ${<}0.001${***} \\\\\n\\addlinespace\nRoBERTa-MNLI & 37.67\\% & 1 & $-$0.17 & n.s. \\\\\n & & 3 & $+$4.17 & 0.003{**} \\\\\n & & 5 & $+$4.33 & 0.037{*} \\\\\n\\addlinespace\nBART-MNLI & 46.17\\% & 1 & 0.00 & n.s. \\\\\n & & 3 & $+$5.17 & ${<}0.001${***} \\\\\n & & 5 & $+$6.33 & 0.003{**} \\\\\n\\bottomrule\n\\end{tabular}\\\\[2pt]\n{\\footnotesize All verifiers fine-tuned on MultiNLI. Unknown recall ${<}3.5\\%$ across all verifiers.}\n\\end{table}\n\n\\paragraph{Three-verifier BH correction.}\n\\label{app:3verifier-bh}\nTable~\\ref{tab:3verifier-bh} applies Benjamini--Hochberg correction across all 15 Mistral-7B verifier--weight conditions ($m{=}15$, $\\alpha{=}0.05$; distinct from the $m{=}12$ cross-generator analysis in \\S\\ref{sec:cross-arch}). Ten of 15 conditions remain significant after correction, confirming that multi-verifier NLI gains are robust to multiple testing.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{BH correction across 3 verifiers $\\times$ 5 weights on Mistral-7B ProofWriter ($n{=}600$, $m{=}15$). \\checkmark: $p_{\\text{BH}} < 0.05$.}\n\\label{tab:3verifier-bh}\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\nVerifier & $w{=}1$ & $w{=}2$ & $w{=}3$ & $w{=}4$ & $w{=}5$ \\\\\n\\midrule\nDeBERTa-MNLI & & \\checkmark & \\checkmark & \\checkmark & \\checkmark \\\\\nRoBERTa-MNLI & & & \\checkmark & \\checkmark & \\checkmark \\\\\nBART-MNLI & & & \\checkmark & \\checkmark & \\checkmark \\\\\n\\bottomrule\n\\end{tabular}\\\\[2pt]\n{\\footnotesize 10/15 significant at $\\alpha{=}0.05$ after BH correction. All $w{=}1$ conditions and RoBERTa $w{=}2$ are non-significant.}\n\\end{table}\n\n\\section{Capability Gap Data Points}\n\\label{app:capability-gap}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.78\\columnwidth]{figures/capability_gap_scatter}\n\\caption{Combo gain vs.\\ capability gap (verifier standalone $-$ generator SC) at $w{=}3$ across three NLI architectures. Gain decreases monotonically (Spearman $\\rho = 1.0$, exact permutation $p = 0.003$, $n{=}6$; four of six conditions share the DeBERTa verifier---see Limitations); significant gains occur only for generators below the verifier's standalone accuracy. Stars: domain-adapted DeBERTa (99.67\\% standalone, Table~\\ref{tab:finetuned-nli}).}\n\\label{fig:capability-gap}\n\\end{figure}\n\nTable~\\ref{tab:cross_generator_nli} reports the controlled cross-generator comparison with DeBERTa-large-mnli on ProofWriter ($n{=}600$). We extend this analysis by pairing Mistral-7B with two additional NLI architectures: BART-large-mnli (46.17\\% standalone, combo $+5.17$\\,pp, $p = 0.0002$) and RoBERTa-large-mnli (37.67\\% standalone, combo $+4.17$\\,pp, $p = 0.003$). All three NLI architectures produce significant gains on Mistral-7B at $w \\geq 3$.\n\nAcross all six ProofWriter verifier-generator pairs at $w{=}3$ (three verifiers $\\times$ Mistral-7B plus three negative-gap generators $\\times$ DeBERTa), combo gain decreases monotonically with the capability gap (Spearman $\\rho = 1.0$, exact permutation $p = 0.003$, $n = 6$; however, four of six conditions share the DeBERTa verifier, which may reduce effective degrees of freedom---see Limitations; Figure~\\ref{fig:capability-gap}). Significant $w{=}3$ gains are observed only for Mistral-7B (SC 39.33\\%, below the verifier); the three above-verifier generators show no significant improvement at any $w$. After BH correction ($m{=}12$), two of twelve conditions survive: Mistral-7B $w{=}3$ (adj.\\ $p = 6.78 \\times 10^{-5}$) and $w{=}5$ (adj.\\ $p = 7.41 \\times 10^{-6}$).\n\n\\paragraph{Robustness check.} Including all nine conditions (three verifiers $\\times$ three weight levels on Mistral-7B) yields Spearman $\\rho = 0.836$ (exact permutation $p = 0.007$, $n = 9$), confirming that the monotonic trend is robust to the choice of weight parameter.\n\n\\paragraph{Full NLI combo with BH correction.}\n\\label{app:nli-combo-full}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Full cross-generator NLI combo results on ProofWriter depth-5 ($n{=}600$) with Benjamini--Hochberg correction ($m{=}12$, $\\alpha{=}0.05$). All conditions use DeBERTa-large-mnli verifier (55.00\\% standalone). Two of twelve conditions survive correction (Mistral-7B $w{=}3$ and $w{=}5$). {***}\\,$p_{\\text{BH}} < 0.001$.}\n\\label{tab:nli-combo-full}\n\\setlength{\\tabcolsep}{3.5pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrrrrl@{}}\n\\toprule\nGenerator & $w$ & Combo (\\%) & $\\Delta$ (pp) & $p_{\\text{raw}}$ & $p_{\\text{BH}}$ & \\\\\n\\midrule\n\\multirow{3}{*}{\\shortstack[l]{Mistral-7B\\\\{\\scriptsize SC\\,39.33\\%, gap\\,$+$15.67}}}\n  & 1 & 40.17 & $+$0.83 & .359 & .721 & \\\\\n  & 3 & 46.00 & $+$6.67 & $1.13{\\times}10^{-5}$ & $6.78{\\times}10^{-5}$ & {***} \\\\\n  & 5 & 50.33 & $+$11.00 & $6.18{\\times}10^{-7}$ & $7.41{\\times}10^{-6}$ & {***} \\\\\n\\addlinespace\n\\multirow{3}{*}{\\shortstack[l]{LLaMA-3.1-8B\\\\{\\scriptsize SC\\,72.50\\%, gap\\,$-$17.50}}}\n  & 1 & 73.33 & $+$0.83 & .359 & .721 & \\\\\n  & 3 & 73.33 & $+$0.83 & .665 & .886 & \\\\\n  & 5 & 72.00 & $-$0.50 & .871 & 1.000 & \\\\\n\\addlinespace\n\\multirow{3}{*}{\\shortstack[l]{Qwen2.5-14B\\\\{\\scriptsize SC\\,74.00\\%, gap\\,$-$19.00}}}\n  & 1 & 74.17 & $+$0.17 & 1.000 & 1.000 & \\\\\n  & 3 & 74.67 & $+$0.67 & .503 & .755 & \\\\\n  & 5 & 75.17 & $+$1.17 & .360 & .721 & \\\\\n\\addlinespace\n\\multirow{3}{*}{\\shortstack[l]{Qwen3-14B\\\\{\\scriptsize SC\\,85.83\\%, gap\\,$-$30.83}}}\n  & 1 & 86.00 & $+$0.17 & 1.000 & 1.000 & \\\\\n  & 3 & 86.33 & $+$0.50 & .453 & .755 & \\\\\n  & 5 & 87.00 & $+$1.17 & .210 & .721 & \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{BART-large-mnli cross-generator results.}\n\n\\begin{table}[h]\n\\centering\n\\small",
      "numLines": 500,
      "startLine": 500,
      "totalLines": 1544
    }
  },
  "sourceToolAssistantUUID": "c6f24b29-6aae-47b7-b656-8e88955ff4e7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Runtime record

_source line 62_

```json
{
  "type": "last-prompt",
  "leafUuid": "255d63ae-11f6-41b5-864b-6ac8e2fc9443",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Runtime record

_source line 63_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper numerics before submission deadline",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Assistant

_source line 64 · 2026-05-24T04:29:17.581Z_

<details><summary>Logged reasoning block</summary>

```text
Let me continue reading the appendix for the multi-seed table and other important data, and also extract the relevant metrics from the registry.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "255d63ae-11f6-41b5-864b-6ac8e2fc9443",
  "isSidechain": false,
  "requestId": "req_011CbLmFS5hQCZqN5afE2Mvw",
  "type": "assistant",
  "uuid": "f70bf1d9-65fa-40b4-94c8-23267b856350",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WbXdVrdUmkfWWuFU2E4brJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17089,
      "cache_read_input_tokens": 67895,
      "output_tokens": 561,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17089,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 561,
          "cache_read_input_tokens": 67895,
          "cache_creation_input_tokens": 17089,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17089
          },
          "type": "message"
        }
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

_source line 65 · 2026-05-24T04:29:17.865Z_

Now I need to find the multi-seed table in the appendix and extract relevant registry metrics. Let me search for key sections.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f70bf1d9-65fa-40b4-94c8-23267b856350",
  "isSidechain": false,
  "requestId": "req_011CbLmFS5hQCZqN5afE2Mvw",
  "type": "assistant",
  "uuid": "ab26a32a-ae10-4019-8f71-8b8fc17b0d0a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WbXdVrdUmkfWWuFU2E4brJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17089,
      "cache_read_input_tokens": 67895,
      "output_tokens": 561,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17089,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 561,
          "cache_read_input_tokens": 67895,
          "cache_creation_input_tokens": 17089,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17089
          },
          "type": "message"
        }
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

_source line 66 · 2026-05-24T04:29:20.541Z_

<details open><summary>🔧 Tool call — Grep · `toolu_016PshmgajByTnfFmB1w22SL`</summary>

```json
{
  "pattern": "tab:multi-seed|multi.seed|Multi-Seed",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ab26a32a-ae10-4019-8f71-8b8fc17b0d0a",
  "isSidechain": false,
  "requestId": "req_011CbLmFS5hQCZqN5afE2Mvw",
  "type": "assistant",
  "uuid": "e9362b40-bfad-4a71-95f5-f86888503fdb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WbXdVrdUmkfWWuFU2E4brJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17089,
      "cache_read_input_tokens": 67895,
      "output_tokens": 561,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17089,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 561,
          "cache_read_input_tokens": 67895,
          "cache_creation_input_tokens": 17089,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17089
          },
          "type": "message"
        }
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

_source line 67 · 2026-05-24T04:29:20.554Z_

<details><summary>↩ Tool result · `toolu_016PshmgajByTnfFmB1w22SL`</summary>

```text
1371:\label{app:multi-seed}
1377:\label{tab:multi-seed}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e9362b40-bfad-4a71-95f5-f86888503fdb",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "93e62a9d-e2c0-45cb-8038-1ec728446cf8",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "1371:\\label{app:multi-seed}\n1377:\\label{tab:multi-seed}",
    "numLines": 2
  },
  "sourceToolAssistantUUID": "e9362b40-bfad-4a71-95f5-f86888503fdb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 68 · 2026-05-24T04:29:27.728Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01LeTepvxTEKaMfGYEc4KMf5`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = data['result']\n\n# Parse the JSON structure\nparsed = json.loads(result)\nexperiments = parsed['data']['experiments']\n\n# Print experiments that have metrics\nfor exp_id, exp in experiments.items():\n    metrics = exp.get('metrics', {})\n    if metrics:\n        print(f'=== {exp_id} ===')\n        print(f'  status: {exp.get(\\\"status\\\", \\\"?\\\")}')\n        for k, v in metrics.items():\n            print(f'  {k}: {v}')\n        print()\n\" 2>&1 | head -400",
  "description": "Extract experiment metrics from registry JSON",
  "timeout": 15000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "93e62a9d-e2c0-45cb-8038-1ec728446cf8",
  "isSidechain": false,
  "requestId": "req_011CbLmFS5hQCZqN5afE2Mvw",
  "type": "assistant",
  "uuid": "714e29f5-3362-488a-9264-3216f02032df",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WbXdVrdUmkfWWuFU2E4brJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17089,
      "cache_read_input_tokens": 67895,
      "output_tokens": 561,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17089,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 561,
          "cache_read_input_tokens": 67895,
          "cache_creation_input_tokens": 17089,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17089
          },
          "type": "message"
        }
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

_source line 69 · 2026-05-24T04:29:27.829Z_

<details><summary>↩ Tool result · `toolu_01LeTepvxTEKaMfGYEc4KMf5`</summary>

```text
=== exp-multi-seed-llama-pw-seed456-v2 ===
  status: DONE
  sc_accuracy: 71.67
  sica_accuracy: 66.17
  delta: -5.5
  n: 600

=== exp-092-llama8b-pw-nli-combo ===
  status: DONE
  n: 600
  sc_accuracy: 0.7
  nli_standalone: 0.55
  capability_gap_pp: -15
  combo_w1: 0.7283
  combo_w3: 0.7417
  combo_w5: 0.7167
  delta_w1_pp: 2.83
  delta_w3_pp: 4.17
  delta_w5_pp: 1.67
  mcnemar_w1_p: 0.0001
  mcnemar_w3_p: 0.0035
  mcnemar_w5_p: 0.4335
  nli_correct_sc_wrong: 120
  sc_correct_nli_wrong: 210

=== exp-multi-seed-mistral-pw ===
  status: DONE
  pw_seed42: {'sc_acc': 40, 'sica_acc': 36.67, 'delta': -3.33, 'n': 600, 'status': 'COMPLETE'}
  pw_seed123: {'sc_acc': 40.83, 'sica_acc': 37.5, 'delta': -3.33, 'n': 600, 'status': 'COMPLETE'}
  pw_seed456: {'sc_acc': 39.83, 'sica_acc': 38.67, 'delta': -1.17, 'n': 600, 'status': 'COMPLETE'}
  pw_seed789: {'sc_acc': 38.83, 'sica_acc': 37.17, 'delta': -1.67, 'n': 600, 'status': 'COMPLETE'}
  mean_4seed: {'sc': 39.87, 'sc_sd': 0.82, 'sica': 37.5, 'sica_sd': 0.85, 'delta': -2.38, 'delta_sd': 1.12, 'n_seeds': 4, 'all_delta_leq_0': True}

=== exp-deberta-ft-combo ===
  status: PREPARING
  standalone_acc: 99.67
  standalone_n: 600
  errors: 2
  d061_corrected: True
  mistral: {'sc_baseline': 39.17, 'w1': {'acc': 42.33, 'delta': 3.17, 'p': '<0.0001'}, 'w3': {'acc': 52.17, 'delta': 13, 'p': '<0.0001'}, 'w5': {'acc': 65.5, 'delta': 26.33, 'p': '<0.0001'}, 'nli_up_sc_down': 365, 'sc_up_nli_down': 2}
  llama8b: {'sc_baseline': 72.5, 'w1': {'acc': 76, 'delta': 3.5, 'p': '<0.0001'}, 'w3': {'acc': 84.17, 'delta': 11.67, 'p': '<0.0001'}, 'w5': {'acc': 91.67, 'delta': 19.17, 'p': '<0.0001'}, 'nli_up_sc_down': 164, 'sc_up_nli_down': 1}
  qwen25_14b: {'sc_baseline': 74, 'w1': {'acc': 75, 'delta': 1, 'p': '<0.05'}, 'w3': {'acc': 78.5, 'delta': 4.5, 'p': '<0.0001'}, 'w5': {'acc': 83, 'delta': 9, 'p': '<0.0001'}}
  qwen3_14b: {'sc_baseline': 85.83, 'w1': {'acc': 86.5, 'delta': 0.67, 'p': 'ns'}, 'w3': {'acc': 88, 'delta': 2.17, 'p': '<0.0001'}, 'w5': {'acc': 90, 'delta': 4.17, 'p': '<0.0001'}}

=== exp-multi-seed-llama-pw ===
  status: DONE
  pw_seed42: {'status': 'running', 'progress': '60/600'}
  pw_seed123: {'status': 'pending'}
  pw_seed456: {'status': 'pending'}

=== exp-multi-seed-llama-folio ===
  status: DONE
  seed123: {'sc_acc': 67.16, 'sica_acc': 63.73, 'delta': -3.43, 'n': 204, 'extraction_rate': 0.959, 'status': 'COMPLETE'}
  seed456: {'status': 'running', 'progress': '125/204'}
  seed789: {'status': 'pending'}

=== exp-multi-seed-mistral-folio ===
  status: PREPARING
  d064_corrected: True
  seed123: {'sc_acc': 54.41, 'sica_acc': 57.35, 'delta': 2.94, 'n': 204, 'source': 'exp052 D064-reeval'}
  seed456: {'sc_acc': 55.88, 'sica_acc': 55.88, 'delta': 0, 'n': 204, 'source': 'exp053 D064-reeval'}
  seed789: {'sc_acc': 59.31, 'sica_acc': 56.86, 'delta': -2.45, 'n': 204, 'source': 'PID 576938 (D064 built-in)'}
  mean_3seed: {'sc': 56.53, 'sc_sd': 2.51, 'sica': 56.7, 'sica_sd': 0.75, 'delta': 0.16, 'delta_sd': 2.7, 'n_seeds': 3}

=== exp-multi-seed-qwen25 ===
  status: PREPARING
  folio_seed42: {'sc_acc': 77.5, 'sica_acc': 75.49, 'delta': -2.01, 'n': 204, 'source': 'baseline'}
  folio_seed123: {'sc_acc': 74.51, 'sica_acc': 73.04, 'delta': -1.47, 'n': 204}
  folio_seed456: {'sc_acc': 74.02, 'sica_acc': 74.02, 'delta': 0, 'n': 204}
  folio_seed789: {'sc_acc': 74.02, 'sica_acc': 72.55, 'delta': -1.47, 'n': 204, 'status': 'FINAL'}
  folio_mean: {'sc': 75.01, 'sica': 73.78, 'delta': -1.24, 'sc_sd': 1.67, 'sica_sd': 1.3, 'delta_sd': 0.86, 'n_seeds': 4}
  pw_seed123: {'status': 'running', 'progress': '190/600', 'pid': 552333, 'gpu': 'cuda:0'}
  pw_seed456: {'status': 'pending', 'note': 'directory has garbage from cuda:1 (max_model_len bug), cuda:0 will overwrite'}
  pw_seed789: {'status': 'pending'}
  pw_eta: 2026-05-23T17:40Z

=== exp-013-constraint-ablation ===
  status: PREPARING
  alpha_ablation: {'mistral_folio': {'alpha_0.1': {'sica_acc': 54.9, 'countonly_acc': 54.9, 'agreement': 100}, 'alpha_0.3': {'sica_acc': 54.9, 'countonly_acc': 54.9, 'agreement': 100}, 'alpha_0.5': {'sica_acc': 54.9, 'countonly_acc': 54.9, 'agreement': 100}, 'alpha_0.7': {'sica_acc': 53.92, 'countonly_acc': 54.41, 'agreement': 99}, 'alpha_0.9': {'sica_acc': 54.9, 'countonly_acc': 55.39, 'agreement': 99}}, 'qwen25_folio': {'alpha_0.1': {'sica_acc': 75, 'countonly_acc': 75, 'agreement': 100}, 'alpha_0.3': {'sica_acc': 75, 'countonly_acc': 75, 'agreement': 100}, 'alpha_0.5': {'sica_acc': 75, 'countonly_acc': 75, 'agreement': 100}, 'alpha_0.7': {'sica_acc': 74.51, 'countonly_acc': 74.51, 'agreement': 100}, 'alpha_0.9': {'sica_acc': 74.02, 'countonly_acc': 74.02, 'agreement': 100}}, 'conclusion': 'Agreement >= 99% across all alpha for both conditions. MAX-SAT equiv count-only is alpha-insensitive.'}

=== exp-folio-2x2-crossmodel ===
  status: DONE
  folio_2x2: {'mistral_gen_mistral_ext': {'SICA': 56.86, 'delta_pp': 0.98, 'BR_mean': 2.7}, 'mistral_gen_qwen3_ext': {'SICA': 59.8, 'delta_pp': 3.92, 'BR_mean': 1.94}, 'qwen3_gen_mistral_ext': {'SICA': 81.86, 'delta_pp': -1.47, 'BR_mean': 2.66}, 'qwen3_gen_qwen3_ext': {'SICA': 84.8, 'delta_pp': 1.47, 'BR_mean': 2.35}}
  SC_mistral: 55.88
  SC_qwen3: 83.33
  kappa_mistral: 0.46
  kappa_qwen3: 0.79
  mcnemar_mistral_ext_p: 0
  mcnemar_qwen3_ext_p: 0

=== exp-d126-crossmodel-sica ===
  status: DONE
  2x2_matrix: {'mistral_gen_mistral_ext': {'SICA': 34.31, 'delta_pp': -5.88, 'BR_mean': 3.44, 'BR_inf_rate': 32.1, 'process_kappa': 0.619}, 'mistral_gen_qwen3_ext': {'SICA': 79.9, 'delta_pp': 39.71, 'BR_mean': 2.85, 'BR_inf_rate': 17.1, 'process_kappa': 0.619}, 'qwen3_gen_mistral_ext': {'SICA': 37.75, 'delta_pp': -49.02, 'BR_mean': 2.16, 'BR_inf_rate': 45.7, 'process_kappa': 0.836}, 'qwen3_gen_qwen3_ext': {'SICA': 79.9, 'delta_pp': -6.86, 'BR_mean': 1.16, 'BR_inf_rate': 63.4, 'process_kappa': 0.836}}
  SC_mistral: 40.2
  SC_qwen3: 86.8
  key_finding: Extractor capability dominates SICA accuracy; BR>1 in all 4 cells confirming SCB universality

=== exp-d135-frontier-scb ===
  status: PREPARING
  gpt4o_self: {'SC': 73.9, 'SICA': 72.1, 'BR_mean': 2.94, 'process_kappa': 0.79, 'answer_kappa': 0.8}
  gpt41_cross_mistral: {'SC': 82.84, 'SICA': 81.37, 'delta_pp': -1.47, 'BR_mean': 2.7, 'process_kappa': 0.79, 'answer_kappa': 0.86}
  gpt55_cross_mistral: {'SC': 84.31, 'SICA': 84.8, 'delta_pp': 0.49, 'BR_mean': 3.48, 'process_kappa': 0.56, 'answer_kappa': 0.96}
  r1distill_cross_mistral: {'SC': 74.51, 'SICA': 76.96, 'delta_pp': 2.45, 'BR_mean': 2.92, 'process_kappa': 0.25, 'answer_kappa': 0.69}
  o3_cross_mistral: {'SC': 82.65, 'SICA': 82.65, 'delta_pp': 0, 'BR_mean': 1.66, 'process_kappa': 0.6, 'answer_kappa': 0.92}
  gemini_interim_95q: {'SC': 87.4, 'cross_SICA': 86.3, 'delta_pp': -1.1, 'process_kappa': 0.79, 'n_questions': 95, 'status': 'extraction_complete_95q'}

=== exp-d126-r1-distill-sica ===
  status: PREPARING
  cross_model_extraction_93: {'n_problems': 93, 'sc_accuracy': 0.7527, 'sica_accuracy': 0.7849, 'delta_pp': 3.22, 'mean_br': 2.97, 'median_br': 2, 'process_kappa_tfidf': 0.2386, 'answer_fleiss_kappa': 0.703, 'extractor': 'Mistral-7B'}
  cross_model_extraction_204: {'n_problems': 204, 'sc_accuracy': 0.7451, 'sica_accuracy': 0.7647, 'delta_pp': 1.96, 'extraction_rate': 0.933, 'total_constraints': 14602, 'unique_constraints': 8653, 'mean_br': 2.85, 'median_br': 2, 'process_kappa_tfidf': 0.2477, 'answer_fleiss_kappa': 0.6944, 'extractor': 'Mistral-7B', 'note': 'Full 204 questions. Cross-model: R1-Distill traces extracted by Mistral-7B. BPE fix applied.'}

=== exp-d134-e6-closed-model ===
  status: PREPARING
  gpt4o_folio: {'completed': 161, 'total': 204, 'sc_accuracy': 0.7391, 'sica_accuracy': 0.7205, 'delta_pp': -1.86, 'n_sica_wrong': 45, 'mean_br': 2.94, 'median_br': 1.91, 'weighted_br': 3.07, 'n_br_finite': 25, 'n_br_infinite': 20, 'process_kappa_tfidf': 0.7884, 'answer_fleiss_kappa': 0.8009}

=== exp-d134-cil ===
  status: PREPARING
  n_pairs_computed: 8
  n_pairs_missing: 2
  spearman_rho: 0.881
  spearman_p: 0.0039
  pearson_r: 0.8481
  pearson_p: 0.0078
  cil_deberta_mistral_pw: 1.67
  cil_sica_mistral_pw: -4.61
  cil_deberta_qwen14b_pw: -0.21
  cil_sica_qwen14b_pw: -4.21
  corrected_v2: Qwen14B canonical SC=74.00% (exp032). Gains: DeBERTa +0.33pp, SICA -2.50pp. Spearman 0.881 p=0.004.

=== exp-d134-baf-decoupled ===
  status: PREPARING
  full_trace_acc: 0.5931
  conservative_acc: 0.5392
  standard_acc: 0.5441
  aggressive_acc: 0.5392
  conservative_br_delta: -0.049
  conservative_wilcoxon_p: 0.122
  conservative_mcnemar_p: 0.001
  aggressive_br_delta: -0.145
  aggressive_wilcoxon_p: 0.256
  aggressive_mcnemar_p: 0.013

=== exp-d134-process-br ===
  status: PREPARING
  position_br_early: 5.37
  position_br_mid: 5.25
  position_br_late: 5.16
  fisher_early_vs_late_p: 0.708
  difficulty_br_easy: 18.82
  difficulty_br_hard: 2.71
  fisher_diff_p: 0
  conditional_br: 5.69
  other_br: 4.91
  fisher_type_p: 0.061

=== exp-d126-drc-folio ===
  status: PREPARING
  sc_acc: 55.88
  full_combo_w3_acc: 58.82
  drc_tau07_w3_acc: 58.33
  drc_tau07_gain_pp: 2.45
  drc_tau07_nli_calls: 71/204
  drc_tau07_cost_pct: 34.8
  drc_tau07_gain_recovery_pct: 83.3
  drc_tau08_w3_acc: 58.82
  drc_tau08_gain_recovery_pct: 100
  drc_tau08_cost_pct: 48.5

=== exp_text_ablation ===
  status: DONE
  t_ext_0.1: {'sica_acc': 57.35, 'delta_pp': 1.47, 'p': 0.581}
  t_ext_0.3: {'sica_acc': 59.31, 'delta_pp': 4.9, 'p': 0.013}
  t_ext_0.5: {'sica_acc': 56.37, 'delta_pp': 0.49, 'p': 1}
  t_ext_0.7: {'sica_acc': 53.43, 'delta_pp': -2.45, 'p': 0.302}
  t_ext_1.0: {'sica_acc': 55.39, 'delta_pp': -0.49, 'p': 1}
  sc_baseline: 55.88

=== exp-091-qwen14b-pw-nli-combo ===
  status: DONE
  n: 600
  sc_accuracy: 0.735
  nli_standalone: 0.55
  capability_gap_pp: -18.5
  combo_w1: 0.7417
  combo_w3: 0.7433
  combo_w5: 0.7533
  delta_w1_pp: 0.67
  delta_w3_pp: 0.83
  delta_w5_pp: 1.83
  mcnemar_w1_p: 0.344
  mcnemar_w3_p: 0.405
  mcnemar_w5_p: 0.144

=== exp-wave3-dir-g-decoupling ===
  status: DONE
  n: 204
  sc_baseline: 0.5441
  sc_correct: 111
  sica_original: 0.5931
  sica_correct: 121
  conservative_accuracy: 0.5392
  conservative_correct: 110
  conservative_avg_trunc_pct: 4.3
  conservative_match_pct: 98.4
  standard_accuracy: 0.5441
  standard_correct: 111
  standard_avg_trunc_pct: 18.9
  standard_match_pct: 98.4
  aggressive_accuracy: 0.5392
  aggressive_correct: 110
  aggressive_avg_trunc_pct: 35.3
  aggressive_match_pct: 100
  best_strategy: standard
  best_delta_vs_sc_pp: 0
  best_delta_vs_sica_pp: -4.9

=== exp-090-r-nli-proofwriter ===
  status: DONE
  n: 600
  sc_accuracy: 0.3933
  sica_accuracy: 0.365
  nli_standalone: 0.55
  combo_w1: 0.4017
  combo_w3: 0.4283
  combo_w5: 0.5
  delta_w1_pp: 0.83
  delta_w3_pp: 3.5
  delta_w5_pp: 10.67
  mcnemar_w1_p: 0.2668
  mcnemar_w1_b: 4
  mcnemar_w1_c: 9
  mcnemar_w3_p: 0.0125
  mcnemar_w3_b: 22
  mcnemar_w3_c: 43
  mcnemar_w5_p: 0.0001
  mcnemar_w5_b: 35
  mcnemar_w5_c: 99
  nli_true_acc: 0.64
  nli_false_acc: 0.975
  nli_unknown_acc: 0.035
  nli_correct_sc_wrong: 274
  sc_correct_nli_wrong: 180
  agreement_acc: 0.808

=== exp-089-oracle-mistral-7b ===
  status: DONE
  sc_accuracy: 0.5588
  oracle_sica_accuracy: 0.8578
  sica_self_accuracy: 0.5931
  delta_oracle_sc_pp: 29.9
  delta_oracle_sica_pp: 26.47
  mcnemar_oracle_vs_sc_p: 9.99e-14
  mcnemar_oracle_vs_sc_b: 63
  mcnemar_oracle_vs_sc_c: 2
  mcnemar_oracle_vs_sica_p: 7.84e-12
  mcnemar_oracle_vs_sica_b: 57
  mcnemar_oracle_vs_sica_c: 3
  z3_gold_agreement: 0.951
  fol_parse_success: 1
  oracle_true_acc: 0.875
  oracle_false_acc: 0.778
  oracle_unknown_acc: 0.913
  n: 204
  utilization_pct: 11.5

=== exp-wave3-dir-r-nli-verifier ===
  status: DONE
  sc_accuracy: 0.5441
  nli_standalone: 0.4951
  combo_w1: 0.5784
  combo_w3: 0.5882
  intersection_acc: 0.6848
  intersection_coverage: 0.451
  delta_w1_pp: 3.43
  delta_w3_pp: 4.41
  mcnemar_w1_p: 0.0391
  mcnemar_w1_b: 1
  mcnemar_w1_c: 8
  mcnemar_w3_p: 0.0784
  mcnemar_w3_b: 6
  mcnemar_w3_c: 15
  ci95_w1: [0.98, 6.37]
  ci95_w3: [0, 8.82]
  nli_false_acc: 0.7143
  sc_false_acc: 0.381
  nli_unknown_acc: 0.1884
  sc_unknown_acc: 0.6812
  model_nli: microsoft/deberta-large-mnli
  n: 204

=== exp-wave3-dir-r-combo-extended ===
  status: DONE
  sc_accuracy: 0.5441
  sica_accuracy: 0.5931
  nli_standalone: 0.4951
  best_combo: nli_sc_vote_w5
  best_combo_acc: 0.6029
  best_delta_sc_pp: 5.88
  best_delta_sica_pp: 0.98
  nli_sc_vote_w3: 0.5882
  intersection_sica_fallback: 0.5931
  intersection_sc_fallback: 0.5735
  oracle_upper_bound: 0.7549
  sica_nli_agreement: 0.475
  agreement_accuracy: 0.701
  n: 204

=== exp-wave3-dir-k-minority ===
  status: DONE
  sc_accuracy: 0.5441
  strict_accuracy: 0.5441
  strict_delta_pp: 0
  moderate_accuracy: 0.4951
  moderate_delta_pp: -4.9
  combined_accuracy: 0.5441
  combined_delta_pp: 0
  minority_consistency_precision: 0.3553
  minority_gt_rate: 0.3373
  majority_gt_rate: 0.488
  moderate_flips: 76
  moderate_correct_flips: 27
  moderate_wrong_flips: 49
  n: 204

=== exp-wave3-dir-i-z3-filter ===
  status: DONE
  n: 204
  sc_baseline: 54.41
  filtered_sc: 53.92
  delta_pp: -0.49
  unsat_traces: 142
  unsat_rate_pct: 5.8
  filter_precision_pct: 49.12
  questions_affected: 7
  improved: 3
  degraded: 4

=== exp-wave3-dir-j-bootstrap ===
  status: DONE
  n: 204
  sc_baseline: 54.41
  r1_accuracy: 56.86
  r1_delta_pp: 2.45
  r1_flips: 32
  r1_improved: 15
  r1_degraded: 10
  r2_accuracy: 54.41
  r3_accuracy: 54.9
  r4_accuracy: 54.41
  r5_accuracy: 52.45
  convergence: oscillating, no convergence

=== exp-cross-model-phase2 ===
  status: DONE
  n: 204
  cross_sc_accuracy: 74.51
  cross_sica_accuracy: 74.02
  delta_pp: -0.49
  mcnemar_p: 1
  config: Mistral-7B(4) + LLaMA-8B(4) + Qwen-7B(4), K=12

=== exp-direction-d-cegis ===
  status: DONE
  n: 204
  sc_baseline: 54.41
  r1_accuracy: 57.84
  r1_delta_pp: 3.43
  r2_accuracy: 57.35
  r2_delta_pp: 2.94
  r3_accuracy: 57.84
  r3_delta_pp: 3.43
  r1_unsat_traces: 127
  r2_unsat_traces: 48
  r3_unsat_traces: 25
  wall_time_min: 51
  extraction_calls: 2448
  refinement_calls: 175

=== exp-confirmation-bias ===
  status: DONE
  bias_ratio: 4.97
  wrong_constraints_when_sica_errs: 0.833
  sica_errors_follow_sc: 0.94

=== exp-cross-model-phase1 ===
  status: DONE
  kappa_cross: 0.422
  kappa_within: 0.532
  eff_k_cross: 2.11
  eff_k_within: 1.52
  accuracy_gain: 0

=== exp-direction-e-abstention ===
  status: DONE
  auroc: 0.673
  coverage_80pct_delta_pp: 4.4
  coverage_60pct_delta_pp: 8.8

=== exp-wild6-kappa-aware-sc ===
  status: DONE
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "714e29f5-3362-488a-9264-3216f02032df",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "00e0fc40-3629-4015-8fcd-d6240ec05995",
  "toolUseResult": {
    "stdout": "=== exp-multi-seed-llama-pw-seed456-v2 ===\n  status: DONE\n  sc_accuracy: 71.67\n  sica_accuracy: 66.17\n  delta: -5.5\n  n: 600\n\n=== exp-092-llama8b-pw-nli-combo ===\n  status: DONE\n  n: 600\n  sc_accuracy: 0.7\n  nli_standalone: 0.55\n  capability_gap_pp: -15\n  combo_w1: 0.7283\n  combo_w3: 0.7417\n  combo_w5: 0.7167\n  delta_w1_pp: 2.83\n  delta_w3_pp: 4.17\n  delta_w5_pp: 1.67\n  mcnemar_w1_p: 0.0001\n  mcnemar_w3_p: 0.0035\n  mcnemar_w5_p: 0.4335\n  nli_correct_sc_wrong: 120\n  sc_correct_nli_wrong: 210\n\n=== exp-multi-seed-mistral-pw ===\n  status: DONE\n  pw_seed42: {'sc_acc': 40, 'sica_acc': 36.67, 'delta': -3.33, 'n': 600, 'status': 'COMPLETE'}\n  pw_seed123: {'sc_acc': 40.83, 'sica_acc': 37.5, 'delta': -3.33, 'n': 600, 'status': 'COMPLETE'}\n  pw_seed456: {'sc_acc': 39.83, 'sica_acc': 38.67, 'delta': -1.17, 'n': 600, 'status': 'COMPLETE'}\n  pw_seed789: {'sc_acc': 38.83, 'sica_acc': 37.17, 'delta': -1.67, 'n': 600, 'status': 'COMPLETE'}\n  mean_4seed: {'sc': 39.87, 'sc_sd': 0.82, 'sica': 37.5, 'sica_sd': 0.85, 'delta': -2.38, 'delta_sd': 1.12, 'n_seeds': 4, 'all_delta_leq_0': True}\n\n=== exp-deberta-ft-combo ===\n  status: PREPARING\n  standalone_acc: 99.67\n  standalone_n: 600\n  errors: 2\n  d061_corrected: True\n  mistral: {'sc_baseline': 39.17, 'w1': {'acc': 42.33, 'delta': 3.17, 'p': '<0.0001'}, 'w3': {'acc': 52.17, 'delta': 13, 'p': '<0.0001'}, 'w5': {'acc': 65.5, 'delta': 26.33, 'p': '<0.0001'}, 'nli_up_sc_down': 365, 'sc_up_nli_down': 2}\n  llama8b: {'sc_baseline': 72.5, 'w1': {'acc': 76, 'delta': 3.5, 'p': '<0.0001'}, 'w3': {'acc': 84.17, 'delta': 11.67, 'p': '<0.0001'}, 'w5': {'acc': 91.67, 'delta': 19.17, 'p': '<0.0001'}, 'nli_up_sc_down': 164, 'sc_up_nli_down': 1}\n  qwen25_14b: {'sc_baseline': 74, 'w1': {'acc': 75, 'delta': 1, 'p': '<0.05'}, 'w3': {'acc': 78.5, 'delta': 4.5, 'p': '<0.0001'}, 'w5': {'acc': 83, 'delta': 9, 'p': '<0.0001'}}\n  qwen3_14b: {'sc_baseline': 85.83, 'w1': {'acc': 86.5, 'delta': 0.67, 'p': 'ns'}, 'w3': {'acc': 88, 'delta': 2.17, 'p': '<0.0001'}, 'w5': {'acc': 90, 'delta': 4.17, 'p': '<0.0001'}}\n\n=== exp-multi-seed-llama-pw ===\n  status: DONE\n  pw_seed42: {'status': 'running', 'progress': '60/600'}\n  pw_seed123: {'status': 'pending'}\n  pw_seed456: {'status': 'pending'}\n\n=== exp-multi-seed-llama-folio ===\n  status: DONE\n  seed123: {'sc_acc': 67.16, 'sica_acc': 63.73, 'delta': -3.43, 'n': 204, 'extraction_rate': 0.959, 'status': 'COMPLETE'}\n  seed456: {'status': 'running', 'progress': '125/204'}\n  seed789: {'status': 'pending'}\n\n=== exp-multi-seed-mistral-folio ===\n  status: PREPARING\n  d064_corrected: True\n  seed123: {'sc_acc': 54.41, 'sica_acc': 57.35, 'delta': 2.94, 'n': 204, 'source': 'exp052 D064-reeval'}\n  seed456: {'sc_acc': 55.88, 'sica_acc': 55.88, 'delta': 0, 'n': 204, 'source': 'exp053 D064-reeval'}\n  seed789: {'sc_acc': 59.31, 'sica_acc': 56.86, 'delta': -2.45, 'n': 204, 'source': 'PID 576938 (D064 built-in)'}\n  mean_3seed: {'sc': 56.53, 'sc_sd': 2.51, 'sica': 56.7, 'sica_sd': 0.75, 'delta': 0.16, 'delta_sd': 2.7, 'n_seeds': 3}\n\n=== exp-multi-seed-qwen25 ===\n  status: PREPARING\n  folio_seed42: {'sc_acc': 77.5, 'sica_acc': 75.49, 'delta': -2.01, 'n': 204, 'source': 'baseline'}\n  folio_seed123: {'sc_acc': 74.51, 'sica_acc': 73.04, 'delta': -1.47, 'n': 204}\n  folio_seed456: {'sc_acc': 74.02, 'sica_acc': 74.02, 'delta': 0, 'n': 204}\n  folio_seed789: {'sc_acc': 74.02, 'sica_acc': 72.55, 'delta': -1.47, 'n': 204, 'status': 'FINAL'}\n  folio_mean: {'sc': 75.01, 'sica': 73.78, 'delta': -1.24, 'sc_sd': 1.67, 'sica_sd': 1.3, 'delta_sd': 0.86, 'n_seeds': 4}\n  pw_seed123: {'status': 'running', 'progress': '190/600', 'pid': 552333, 'gpu': 'cuda:0'}\n  pw_seed456: {'status': 'pending', 'note': 'directory has garbage from cuda:1 (max_model_len bug), cuda:0 will overwrite'}\n  pw_seed789: {'status': 'pending'}\n  pw_eta: 2026-05-23T17:40Z\n\n=== exp-013-constraint-ablation ===\n  status: PREPARING\n  alpha_ablation: {'mistral_folio': {'alpha_0.1': {'sica_acc': 54.9, 'countonly_acc': 54.9, 'agreement': 100}, 'alpha_0.3': {'sica_acc': 54.9, 'countonly_acc': 54.9, 'agreement': 100}, 'alpha_0.5': {'sica_acc': 54.9, 'countonly_acc': 54.9, 'agreement': 100}, 'alpha_0.7': {'sica_acc': 53.92, 'countonly_acc': 54.41, 'agreement': 99}, 'alpha_0.9': {'sica_acc': 54.9, 'countonly_acc': 55.39, 'agreement': 99}}, 'qwen25_folio': {'alpha_0.1': {'sica_acc': 75, 'countonly_acc': 75, 'agreement': 100}, 'alpha_0.3': {'sica_acc': 75, 'countonly_acc': 75, 'agreement': 100}, 'alpha_0.5': {'sica_acc': 75, 'countonly_acc': 75, 'agreement': 100}, 'alpha_0.7': {'sica_acc': 74.51, 'countonly_acc': 74.51, 'agreement': 100}, 'alpha_0.9': {'sica_acc': 74.02, 'countonly_acc': 74.02, 'agreement': 100}}, 'conclusion': 'Agreement >= 99% across all alpha for both conditions. MAX-SAT equiv count-only is alpha-insensitive.'}\n\n=== exp-folio-2x2-crossmodel ===\n  status: DONE\n  folio_2x2: {'mistral_gen_mistral_ext': {'SICA': 56.86, 'delta_pp': 0.98, 'BR_mean': 2.7}, 'mistral_gen_qwen3_ext': {'SICA': 59.8, 'delta_pp': 3.92, 'BR_mean': 1.94}, 'qwen3_gen_mistral_ext': {'SICA': 81.86, 'delta_pp': -1.47, 'BR_mean': 2.66}, 'qwen3_gen_qwen3_ext': {'SICA': 84.8, 'delta_pp': 1.47, 'BR_mean': 2.35}}\n  SC_mistral: 55.88\n  SC_qwen3: 83.33\n  kappa_mistral: 0.46\n  kappa_qwen3: 0.79\n  mcnemar_mistral_ext_p: 0\n  mcnemar_qwen3_ext_p: 0\n\n=== exp-d126-crossmodel-sica ===\n  status: DONE\n  2x2_matrix: {'mistral_gen_mistral_ext': {'SICA': 34.31, 'delta_pp': -5.88, 'BR_mean': 3.44, 'BR_inf_rate': 32.1, 'process_kappa': 0.619}, 'mistral_gen_qwen3_ext': {'SICA': 79.9, 'delta_pp': 39.71, 'BR_mean': 2.85, 'BR_inf_rate': 17.1, 'process_kappa': 0.619}, 'qwen3_gen_mistral_ext': {'SICA': 37.75, 'delta_pp': -49.02, 'BR_mean': 2.16, 'BR_inf_rate': 45.7, 'process_kappa': 0.836}, 'qwen3_gen_qwen3_ext': {'SICA': 79.9, 'delta_pp': -6.86, 'BR_mean': 1.16, 'BR_inf_rate': 63.4, 'process_kappa': 0.836}}\n  SC_mistral: 40.2\n  SC_qwen3: 86.8\n  key_finding: Extractor capability dominates SICA accuracy; BR>1 in all 4 cells confirming SCB universality\n\n=== exp-d135-frontier-scb ===\n  status: PREPARING\n  gpt4o_self: {'SC': 73.9, 'SICA': 72.1, 'BR_mean': 2.94, 'process_kappa': 0.79, 'answer_kappa': 0.8}\n  gpt41_cross_mistral: {'SC': 82.84, 'SICA': 81.37, 'delta_pp': -1.47, 'BR_mean': 2.7, 'process_kappa': 0.79, 'answer_kappa': 0.86}\n  gpt55_cross_mistral: {'SC': 84.31, 'SICA': 84.8, 'delta_pp': 0.49, 'BR_mean': 3.48, 'process_kappa': 0.56, 'answer_kappa': 0.96}\n  r1distill_cross_mistral: {'SC': 74.51, 'SICA': 76.96, 'delta_pp': 2.45, 'BR_mean': 2.92, 'process_kappa': 0.25, 'answer_kappa': 0.69}\n  o3_cross_mistral: {'SC': 82.65, 'SICA': 82.65, 'delta_pp': 0, 'BR_mean': 1.66, 'process_kappa': 0.6, 'answer_kappa': 0.92}\n  gemini_interim_95q: {'SC': 87.4, 'cross_SICA': 86.3, 'delta_pp': -1.1, 'process_kappa': 0.79, 'n_questions': 95, 'status': 'extraction_complete_95q'}\n\n=== exp-d126-r1-distill-sica ===\n  status: PREPARING\n  cross_model_extraction_93: {'n_problems': 93, 'sc_accuracy': 0.7527, 'sica_accuracy': 0.7849, 'delta_pp': 3.22, 'mean_br': 2.97, 'median_br': 2, 'process_kappa_tfidf': 0.2386, 'answer_fleiss_kappa': 0.703, 'extractor': 'Mistral-7B'}\n  cross_model_extraction_204: {'n_problems': 204, 'sc_accuracy': 0.7451, 'sica_accuracy': 0.7647, 'delta_pp': 1.96, 'extraction_rate': 0.933, 'total_constraints': 14602, 'unique_constraints': 8653, 'mean_br': 2.85, 'median_br': 2, 'process_kappa_tfidf': 0.2477, 'answer_fleiss_kappa': 0.6944, 'extractor': 'Mistral-7B', 'note': 'Full 204 questions. Cross-model: R1-Distill traces extracted by Mistral-7B. BPE fix applied.'}\n\n=== exp-d134-e6-closed-model ===\n  status: PREPARING\n  gpt4o_folio: {'completed': 161, 'total': 204, 'sc_accuracy': 0.7391, 'sica_accuracy': 0.7205, 'delta_pp': -1.86, 'n_sica_wrong': 45, 'mean_br': 2.94, 'median_br': 1.91, 'weighted_br': 3.07, 'n_br_finite': 25, 'n_br_infinite': 20, 'process_kappa_tfidf': 0.7884, 'answer_fleiss_kappa': 0.8009}\n\n=== exp-d134-cil ===\n  status: PREPARING\n  n_pairs_computed: 8\n  n_pairs_missing: 2\n  spearman_rho: 0.881\n  spearman_p: 0.0039\n  pearson_r: 0.8481\n  pearson_p: 0.0078\n  cil_deberta_mistral_pw: 1.67\n  cil_sica_mistral_pw: -4.61\n  cil_deberta_qwen14b_pw: -0.21\n  cil_sica_qwen14b_pw: -4.21\n  corrected_v2: Qwen14B canonical SC=74.00% (exp032). Gains: DeBERTa +0.33pp, SICA -2.50pp. Spearman 0.881 p=0.004.\n\n=== exp-d134-baf-decoupled ===\n  status: PREPARING\n  full_trace_acc: 0.5931\n  conservative_acc: 0.5392\n  standard_acc: 0.5441\n  aggressive_acc: 0.5392\n  conservative_br_delta: -0.049\n  conservative_wilcoxon_p: 0.122\n  conservative_mcnemar_p: 0.001\n  aggressive_br_delta: -0.145\n  aggressive_wilcoxon_p: 0.256\n  aggressive_mcnemar_p: 0.013\n\n=== exp-d134-process-br ===\n  status: PREPARING\n  position_br_early: 5.37\n  position_br_mid: 5.25\n  position_br_late: 5.16\n  fisher_early_vs_late_p: 0.708\n  difficulty_br_easy: 18.82\n  difficulty_br_hard: 2.71\n  fisher_diff_p: 0\n  conditional_br: 5.69\n  other_br: 4.91\n  fisher_type_p: 0.061\n\n=== exp-d126-drc-folio ===\n  status: PREPARING\n  sc_acc: 55.88\n  full_combo_w3_acc: 58.82\n  drc_tau07_w3_acc: 58.33\n  drc_tau07_gain_pp: 2.45\n  drc_tau07_nli_calls: 71/204\n  drc_tau07_cost_pct: 34.8\n  drc_tau07_gain_recovery_pct: 83.3\n  drc_tau08_w3_acc: 58.82\n  drc_tau08_gain_recovery_pct: 100\n  drc_tau08_cost_pct: 48.5\n\n=== exp_text_ablation ===\n  status: DONE\n  t_ext_0.1: {'sica_acc': 57.35, 'delta_pp': 1.47, 'p': 0.581}\n  t_ext_0.3: {'sica_acc': 59.31, 'delta_pp': 4.9, 'p': 0.013}\n  t_ext_0.5: {'sica_acc': 56.37, 'delta_pp': 0.49, 'p': 1}\n  t_ext_0.7: {'sica_acc': 53.43, 'delta_pp': -2.45, 'p': 0.302}\n  t_ext_1.0: {'sica_acc': 55.39, 'delta_pp': -0.49, 'p': 1}\n  sc_baseline: 55.88\n\n=== exp-091-qwen14b-pw-nli-combo ===\n  status: DONE\n  n: 600\n  sc_accuracy: 0.735\n  nli_standalone: 0.55\n  capability_gap_pp: -18.5\n  combo_w1: 0.7417\n  combo_w3: 0.7433\n  combo_w5: 0.7533\n  delta_w1_pp: 0.67\n  delta_w3_pp: 0.83\n  delta_w5_pp: 1.83\n  mcnemar_w1_p: 0.344\n  mcnemar_w3_p: 0.405\n  mcnemar_w5_p: 0.144\n\n=== exp-wave3-dir-g-decoupling ===\n  status: DONE\n  n: 204\n  sc_baseline: 0.5441\n  sc_correct: 111\n  sica_original: 0.5931\n  sica_correct: 121\n  conservative_accuracy: 0.5392\n  conservative_correct: 110\n  conservative_avg_trunc_pct: 4.3\n  conservative_match_pct: 98.4\n  standard_accuracy: 0.5441\n  standard_correct: 111\n  standard_avg_trunc_pct: 18.9\n  standard_match_pct: 98.4\n  aggressive_accuracy: 0.5392\n  aggressive_correct: 110\n  aggressive_avg_trunc_pct: 35.3\n  aggressive_match_pct: 100\n  best_strategy: standard\n  best_delta_vs_sc_pp: 0\n  best_delta_vs_sica_pp: -4.9\n\n=== exp-090-r-nli-proofwriter ===\n  status: DONE\n  n: 600\n  sc_accuracy: 0.3933\n  sica_accuracy: 0.365\n  nli_standalone: 0.55\n  combo_w1: 0.4017\n  combo_w3: 0.4283\n  combo_w5: 0.5\n  delta_w1_pp: 0.83\n  delta_w3_pp: 3.5\n  delta_w5_pp: 10.67\n  mcnemar_w1_p: 0.2668\n  mcnemar_w1_b: 4\n  mcnemar_w1_c: 9\n  mcnemar_w3_p: 0.0125\n  mcnemar_w3_b: 22\n  mcnemar_w3_c: 43\n  mcnemar_w5_p: 0.0001\n  mcnemar_w5_b: 35\n  mcnemar_w5_c: 99\n  nli_true_acc: 0.64\n  nli_false_acc: 0.975\n  nli_unknown_acc: 0.035\n  nli_correct_sc_wrong: 274\n  sc_correct_nli_wrong: 180\n  agreement_acc: 0.808\n\n=== exp-089-oracle-mistral-7b ===\n  status: DONE\n  sc_accuracy: 0.5588\n  oracle_sica_accuracy: 0.8578\n  sica_self_accuracy: 0.5931\n  delta_oracle_sc_pp: 29.9\n  delta_oracle_sica_pp: 26.47\n  mcnemar_oracle_vs_sc_p: 9.99e-14\n  mcnemar_oracle_vs_sc_b: 63\n  mcnemar_oracle_vs_sc_c: 2\n  mcnemar_oracle_vs_sica_p: 7.84e-12\n  mcnemar_oracle_vs_sica_b: 57\n  mcnemar_oracle_vs_sica_c: 3\n  z3_gold_agreement: 0.951\n  fol_parse_success: 1\n  oracle_true_acc: 0.875\n  oracle_false_acc: 0.778\n  oracle_unknown_acc: 0.913\n  n: 204\n  utilization_pct: 11.5\n\n=== exp-wave3-dir-r-nli-verifier ===\n  status: DONE\n  sc_accuracy: 0.5441\n  nli_standalone: 0.4951\n  combo_w1: 0.5784\n  combo_w3: 0.5882\n  intersection_acc: 0.6848\n  intersection_coverage: 0.451\n  delta_w1_pp: 3.43\n  delta_w3_pp: 4.41\n  mcnemar_w1_p: 0.0391\n  mcnemar_w1_b: 1\n  mcnemar_w1_c: 8\n  mcnemar_w3_p: 0.0784\n  mcnemar_w3_b: 6\n  mcnemar_w3_c: 15\n  ci95_w1: [0.98, 6.37]\n  ci95_w3: [0, 8.82]\n  nli_false_acc: 0.7143\n  sc_false_acc: 0.381\n  nli_unknown_acc: 0.1884\n  sc_unknown_acc: 0.6812\n  model_nli: microsoft/deberta-large-mnli\n  n: 204\n\n=== exp-wave3-dir-r-combo-extended ===\n  status: DONE\n  sc_accuracy: 0.5441\n  sica_accuracy: 0.5931\n  nli_standalone: 0.4951\n  best_combo: nli_sc_vote_w5\n  best_combo_acc: 0.6029\n  best_delta_sc_pp: 5.88\n  best_delta_sica_pp: 0.98\n  nli_sc_vote_w3: 0.5882\n  intersection_sica_fallback: 0.5931\n  intersection_sc_fallback: 0.5735\n  oracle_upper_bound: 0.7549\n  sica_nli_agreement: 0.475\n  agreement_accuracy: 0.701\n  n: 204\n\n=== exp-wave3-dir-k-minority ===\n  status: DONE\n  sc_accuracy: 0.5441\n  strict_accuracy: 0.5441\n  strict_delta_pp: 0\n  moderate_accuracy: 0.4951\n  moderate_delta_pp: -4.9\n  combined_accuracy: 0.5441\n  combined_delta_pp: 0\n  minority_consistency_precision: 0.3553\n  minority_gt_rate: 0.3373\n  majority_gt_rate: 0.488\n  moderate_flips: 76\n  moderate_correct_flips: 27\n  moderate_wrong_flips: 49\n  n: 204\n\n=== exp-wave3-dir-i-z3-filter ===\n  status: DONE\n  n: 204\n  sc_baseline: 54.41\n  filtered_sc: 53.92\n  delta_pp: -0.49\n  unsat_traces: 142\n  unsat_rate_pct: 5.8\n  filter_precision_pct: 49.12\n  questions_affected: 7\n  improved: 3\n  degraded: 4\n\n=== exp-wave3-dir-j-bootstrap ===\n  status: DONE\n  n: 204\n  sc_baseline: 54.41\n  r1_accuracy: 56.86\n  r1_delta_pp: 2.45\n  r1_flips: 32\n  r1_improved: 15\n  r1_degraded: 10\n  r2_accuracy: 54.41\n  r3_accuracy: 54.9\n  r4_accuracy: 54.41\n  r5_accuracy: 52.45\n  convergence: oscillating, no convergence\n\n=== exp-cross-model-phase2 ===\n  status: DONE\n  n: 204\n  cross_sc_accuracy: 74.51\n  cross_sica_accuracy: 74.02\n  delta_pp: -0.49\n  mcnemar_p: 1\n  config: Mistral-7B(4) + LLaMA-8B(4) + Qwen-7B(4), K=12\n\n=== exp-direction-d-cegis ===\n  status: DONE\n  n: 204\n  sc_baseline: 54.41\n  r1_accuracy: 57.84\n  r1_delta_pp: 3.43\n  r2_accuracy: 57.35\n  r2_delta_pp: 2.94\n  r3_accuracy: 57.84\n  r3_delta_pp: 3.43\n  r1_unsat_traces: 127\n  r2_unsat_traces: 48\n  r3_unsat_traces: 25\n  wall_time_min: 51\n  extraction_calls: 2448\n  refinement_calls: 175\n\n=== exp-confirmation-bias ===\n  status: DONE\n  bias_ratio: 4.97\n  wrong_constraints_when_sica_errs: 0.833\n  sica_errors_follow_sc: 0.94\n\n=== exp-cross-model-phase1 ===\n  status: DONE\n  kappa_cross: 0.422\n  kappa_within: 0.532\n  eff_k_cross: 2.11\n  eff_k_within: 1.52\n  accuracy_gain: 0\n\n=== exp-direction-e-abstention ===\n  status: DONE\n  auroc: 0.673\n  coverage_80pct_delta_pp: 4.4\n  coverage_60pct_delta_pp: 8.8\n\n=== exp-wild6-kappa-aware-sc ===\n  status: DONE",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "714e29f5-3362-488a-9264-3216f02032df",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Runtime record

_source line 70 · 2026-05-24T04:29:27.848Z_

```json
{
  "parentUuid": "00e0fc40-3629-4015-8fcd-d6240ec05995",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "a19169c4-ee26-45c2-bac9-3f1681e87dbf",
  "timestamp": "2026-05-24T04:29:27.848Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---


### Runtime record

_source line 71_

```json
{
  "type": "last-prompt",
  "leafUuid": "a19169c4-ee26-45c2-bac9-3f1681e87dbf",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Runtime record

_source line 72_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper numerics before submission deadline",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Assistant

_source line 73 · 2026-05-24T04:29:33.269Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the multi-seed table in the appendix and get more registry data. I also need to look at key numbers more carefully.

Let me also check some specific numbers. Let me read the multi-seed section of the appendix and get additional registry data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a19169c4-ee26-45c2-bac9-3f1681e87dbf",
  "isSidechain": false,
  "requestId": "req_011CbLmGu2Te5936NhsEav49",
  "type": "assistant",
  "uuid": "6394368b-f51e-42a0-b583-d3afd35f03e7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015oFprcWwB8aY5H34fZibnN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8277,
      "cache_read_input_tokens": 84984,
      "output_tokens": 1190,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8277,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1190,
          "cache_read_input_tokens": 84984,
          "cache_creation_input_tokens": 8277,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8277
          },
          "type": "message"
        }
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

_source line 74 · 2026-05-24T04:29:34.252Z_

Let me read the multi-seed table and get more registry data for cross-referencing.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6394368b-f51e-42a0-b583-d3afd35f03e7",
  "isSidechain": false,
  "requestId": "req_011CbLmGu2Te5936NhsEav49",
  "type": "assistant",
  "uuid": "429d1e88-6361-4159-9408-d56c5d3bc3c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015oFprcWwB8aY5H34fZibnN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8277,
      "cache_read_input_tokens": 84984,
      "output_tokens": 1190,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8277,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1190,
          "cache_read_input_tokens": 84984,
          "cache_creation_input_tokens": 8277,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8277
          },
          "type": "message"
        }
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

_source line 75 · 2026-05-24T04:29:36.620Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SQHv28XvgVeihXCveKZBm9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
  "offset": 1360,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "429d1e88-6361-4159-9408-d56c5d3bc3c7",
  "isSidechain": false,
  "requestId": "req_011CbLmGu2Te5936NhsEav49",
  "type": "assistant",
  "uuid": "3ed49da8-9ed0-4cef-9e31-985de818400f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015oFprcWwB8aY5H34fZibnN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8277,
      "cache_read_input_tokens": 84984,
      "output_tokens": 1190,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8277,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1190,
          "cache_read_input_tokens": 84984,
          "cache_creation_input_tokens": 8277,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8277
          },
          "type": "message"
        }
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

_source line 76 · 2026-05-24T04:29:36.629Z_

<details><summary>↩ Tool result · `toolu_01SQHv28XvgVeihXCveKZBm9`</summary>

```text
1360	$0.3^\dagger$ & 59.31 & $+$3.43 & 68.8 \\
1361	0.5 & 56.37 & $+$0.49 & 68.2 \\
1362	0.7 & 53.43 & $-$2.45 & 67.3 \\
1363	1.0 & 55.39 & $-$0.49 & 65.2 \\
1364	\bottomrule
1365	\end{tabular}
1366	\end{table}
1367	
1368	Controlling for the trace set (excluding $T_{\text{ext}} = 0.3$, which uses a different seed), all conditions yield $\Delta \leq +1.47$\,pp (n.s.), indicating that extraction temperature has no significant effect on SICA accuracy. This supports the structural nature of symbolic confirmation bias: the bottleneck is what gets extracted, not the temperature at which extraction occurs.
1369	
1370	\paragraph{Multi-seed replication.}
1371	\label{app:multi-seed}
1372	
1373	\begin{table}[h]
1374	\centering
1375	\small
1376	\caption{Multi-seed replication results across four model$\times$dataset conditions. Each row uses an independent seed with fresh traces ($K{=}12$, $T{=}0.7$). Mistral-7B$\times$FOLIO shows directionally unstable $\Delta$ ($+0.16 \pm 2.70$\,pp); all ProofWriter conditions show consistently negative $\Delta$ across all seeds ($p < .001$ for LLaMA-8B and Mistral-7B). Qwen3-14B results pending.}
1377	\label{tab:multi-seed}
1378	\resizebox{\columnwidth}{!}{%
1379	\begin{tabular}{@{}lrrrr@{}}
1380	\toprule
1381	Seed & SC (\%) & SICA (\%) & $\Delta$ (pp) \\
1382	\midrule
1383	\multicolumn{4}{@{}l}{\textit{Mistral-7B $\times$ FOLIO ($n{=}204$)\textsuperscript{a}}} \\
1384	123 & 54.41 & 57.35 & $+$2.94 \\
1385	456 & 55.88 & 55.88 & 0.00 \\
1386	789 & 59.31 & 56.86 & $-$2.45 \\
1387	\midrule
1388	Mean $\pm$ SD & 56.53 $\pm$ 2.51 & 56.70 $\pm$ 0.75 & $+$0.16 $\pm$ 2.70 \\
1389	\midrule
1390	\multicolumn{4}{@{}l}{\textit{Qwen2.5-14B $\times$ FOLIO ($n{=}204$)}} \\
1391	42 & 77.50 & 75.49 & $-$2.01 \\
1392	123 & 74.51 & 73.04 & $-$1.47 \\
1393	456 & 74.02 & 74.02 & 0.00 \\
1394	789 & 74.02 & 72.55 & $-$1.47 \\
1395	\midrule
1396	Mean $\pm$ SD & 75.01 $\pm$ 1.67 & 73.78 $\pm$ 1.30 & $-$1.24 $\pm$ 0.86 \\
1397	\midrule
1398	\multicolumn{4}{@{}l}{\textit{Mistral-7B $\times$ ProofWriter ($n{=}600$)}} \\
1399	42  & 39.33 & 36.50 & $-$2.83 \\
1400	123 & 40.83 & 37.50 & $-$3.33 \\
1401	456 & 39.83 & 38.50 & $-$1.33 \\
1402	789 & 38.83 & 37.17 & $-$1.67 \\
1403	\midrule
1404	Mean $\pm$ SD & 39.70 $\pm$ 0.85 & 37.42 $\pm$ 0.83 & $-$2.29 $\pm$ 0.95 \\
1405	\midrule
1406	\multicolumn{4}{@{}l}{\textit{LLaMA-3.1-8B $\times$ ProofWriter ($n{=}600$)}} \\
1407	42  & 72.50 & 65.00 & $-$7.50 \\
1408	123 & 71.33 & 64.00 & $-$7.33 \\
1409	456 & 71.67 & 66.17 & $-$5.50 \\
1410	789 & 71.17 & 66.50 & $-$4.67 \\
1411	\midrule
1412	Mean $\pm$ SD & 71.67 $\pm$ 0.59 & 65.42 $\pm$ 1.14 & $-$6.25 $\pm$ 1.34 \\
1413	\bottomrule
1414	\end{tabular}}
1415	\vspace{2pt}
1416	{\footnotesize \textsuperscript{a}Original baseline (exp033) used no fixed seed and is excluded from seed statistics.}
1417	\end{table}
1418	
1419	On ProofWriter, all eight Mistral-7B and LLaMA-8B seeds yield negative $\Delta$ (range $-1.33$ to $-7.50$\,pp), with all LLaMA-8B McNemar tests reaching $p < .001$. The consistency across seeds confirms that negative $\Delta$ on ProofWriter is not an artifact of any single random sample.
1420	
1421	\subsection{Sub-population Analysis}
1422	\label{app:subpopulation}
1423	
1424	\begin{table}[h]
1425	\centering
1426	\small
1427	\caption{SICA vs.\ SC accuracy by gold-label type (Mistral-7B). Corrected SC baseline uses alphabetical tiebreaking. $\Delta$\,pp = SICA $-$ SC. $p$-values from exact McNemar test (two-sided).}
1428	\label{tab:subpop-answer-type}
1429	\resizebox{\columnwidth}{!}{%
1430	\begin{tabular}{ll rrr rr}
1431	\toprule
1432	\textbf{Dataset} & \textbf{Label} & $n$ & \textbf{SC} & \textbf{SICA} & $\Delta$\,pp & $p$ \\
1433	\midrule
1434	\multirow{4}{*}{FOLIO-204}
1435	 & True    &  72 & 56.9 & 62.5 & $+$5.6 & .125 \\
1436	 & False   &  63 & 42.9 & 42.9 & $\pm$0.0 & 1.0\hphantom{00} \\
1437	 & Unknown &  69 & 66.7 & 71.0 & $+$4.3 & .250 \\
1438	 & \textit{Overall} & 204 & 55.9 & 59.3 & $+$3.4 & .092 \\
1439	\midrule
1440	\multirow{4}{*}{PW-600}
1441	 & True    & 200 &  8.5 &  6.0 & $-$2.5 & .063 \\
1442	 & False   & 200 & 19.5 & 14.5 & $-$5.0 & .076 \\
1443	 & Unknown & 200 & 90.0 & 89.0 & $-$1.0 & .774 \\
1444	 & \textit{Overall} & 600 & 39.3 & 36.5 & $-$2.8 & .014\rlap{*} \\
1445	\bottomrule
1446	\end{tabular}}
1447	\end{table}
1448	
1449	\begin{table}[h]
1450	\centering
1451	\small
1452	\caption{SICA vs.\ SC accuracy by extracted constraint count tertile (Mistral-7B). Corrected SC baseline (alphabetical tiebreaking). Constraint counts are unique deduplicated constraints per problem.}
1453	\label{tab:subpop-constraint}
1454	\resizebox{\columnwidth}{!}{%
1455	\begin{tabular}{ll rr rrr rr}
1456	\toprule
1457	\textbf{Dataset} & \textbf{Tertile} & $n$ & $\bar{c}$ & \textbf{SC} & \textbf{SICA} & $\Delta$\,pp & $p$ \\
1458	\midrule
1459	\multirow{3}{*}{FOLIO-204}
1460	 & Low \scriptsize{[0--32]}   &  74 & 21.7 & 62.2 & 63.5 & $+$1.4 & 1.0\hphantom{00} \\
1461	 & Mid \scriptsize{[33--47]}  &  64 & 39.7 & 50.0 & 59.4 & $+$9.4 & .031\rlap{*} \\
1462	 & High \scriptsize{[48--83]} &  66 & 58.7 & 54.5 & 54.5 & $\pm$0.0 & 1.0\hphantom{00} \\
1463	\midrule
1464	\multirow{3}{*}{PW-600}
1465	 & Low \scriptsize{[0--39]}   & 212 & 28.8 & 43.9 & 39.6 & $-$4.3 & .078 \\
1466	 & Mid \scriptsize{[40--52]}  & 196 & 45.8 & 40.8 & 37.2 & $-$3.6 & .143 \\
1467	 & High \scriptsize{[53--99]} & 192 & 63.7 & 32.8 & 32.3 & $-$0.5 & 1.0\hphantom{00} \\
1468	\bottomrule
1469	\end{tabular}}
1470	\end{table}
1471	
1472	On FOLIO-204 with the corrected SC baseline (alphabetical tiebreaking), SICA improves over SC by $+$3.4\,pp overall (55.9\% $\to$ 59.3\%), though the aggregate McNemar test is marginally non-significant ($p{=}.092$).
1473	The gain concentrates in the mid-constraint tertile ($+$9.4\,pp, $p{=}.031$), where sufficient symbolic evidence exists for MaxSAT to meaningfully re-rank answers; in the low- and high-constraint groups the methods perform comparably.
1474	On ProofWriter-600, SICA shows a small uniform degradation consistent with the main results, attenuating in the high-constraint tertile ($\Delta{=}{-}0.5$\,pp, $p{=}1.0$).
1475	We note that with six subgroup tests, one significant result at $\alpha{=}0.05$ is expected by chance; the mid-constraint finding should be interpreted as exploratory.
1476	
1477	\paragraph{Individual intervention significance.}
1478	\label{app:intervention-individual}
1479	Of the 27 training-free remediation strategies (Figure~\ref{fig:interventions-summary}), the two largest positive effects are Cross-model Qwen3$\to$Mistral ($+0.98$\,pp) and Generational ($+0.49$\,pp); neither approaches statistical significance ($p > 0.5$ for both). The largest negative effects are LLM-Debate ($-18.6$\,pp, $p < 0.001$) and Contrastive Scoring ($-9.3$\,pp, $p < 0.001$). After BH correction across all 27 comparisons, only these two negative results remain significant. No strategy produces a significant positive effect under any correction procedure.
1480	
1481	\section{Extended Discussion}
1482	\label{app:extended-discussion}
1483	\label{app:limitations-extended}
1484	
1485	\paragraph{SCB versus CoT unfaithfulness.}
1486	SCB is distinct from CoT unfaithfulness \citep{turpin2023language} and CoT-level confirmation bias \citep{wan2025unveiling, jhaveri2026failing}. CoT unfaithfulness concerns whether stated reasoning reflects actual computation; SCB concerns whether \emph{self-extracted formal constraints} mirror the model's answer distribution. Even if traces were perfectly faithful, self-extraction would still inherit the distributional bias---the constraint $P(\text{answer\_A})$ reflects vote share, not logical validity. The shuffle control (\S\ref{sec:confirmation-bias}) confirms this: randomizing constraint--answer associations preserves BR, showing the bias is in the trace-count distribution, not in extraction-specific errors. However, if traces are unfaithful, the mirage may be worse than our measurements suggest, because constraints would reflect not the model's reasoning but its post-hoc rationalization.
1487	
1488	\paragraph{Implications for neuro-symbolic practitioners.}
1489	Our results do not imply that neuro-symbolic methods are inherently flawed---they imply that \emph{self-extracted} constraints cannot provide independent verification. The key distinction is \emph{when} formalization occurs relative to answer generation. Specification-generation approaches (e.g., SatLM \citep{ye2024satlm}, Logic-LM \citep{pan2023logiclm}) formalize the problem \emph{before} generating candidate answers, avoiding the extraction bottleneck; SatLM's success confirms that the formal verification mechanism is sound when constraints are independently derived. Trace-extraction (this work) operates post-hoc on reasoning traces that already contain candidates, inheriting the distributional prior that generates SCB. When post-hoc verification is unavoidable, practitioners should employ external verifiers from a different architecture family (\S\ref{sec:cross-arch}) and use the diagnostic framework in \S\ref{sec:discussion} to assess feasibility before deployment. The SCB diagnostic toolkit (below) provides detailed computation methods and threshold recommendations.
1490	
1491	\paragraph{Test-time scaling implications.}
1492	Vote diversity decreases with model capability: $K_\text{eff}$ drops from 3.62 (Mistral-7B on ProofWriter) to 1.09 (Qwen3-14B thinking mode). This creates a fundamental tension for o1/R1-style scaling \citep{guo2025deepseekr1}: longer reasoning chains produce more coherent but less diverse traces, reducing the marginal value of additional samples. Our Process-$\kappa$ analysis (\S\ref{sec:process-kappa}) reveals that this homogenization operates at the reasoning-process level, not just answer level---traces that disagree on final answers still share 69\% of their reasoning structure. Cross-architecture ensembles offer a path forward, but the capability-gap condition (\S\ref{sec:cross-arch}) implies that the verifier must be genuinely complementary, not just different.
1493	
1494	\paragraph{SCB diagnostic toolkit.}
1495	\label{app:diagnostic-toolkit}
1496	We recommend four zero-cost diagnostics, computable from sampled traces alone, to predict whether symbolic self-verification will help or hurt before deployment.
1497	\emph{Bias Ratio} (BR; \S\ref{sec:confirmation-bias}): for each problem, compute the fraction of constraints supporting the majority answer, divided by majority vote share. $\text{BR} > 1$ indicates constraints are biased toward the majority; $\text{BR} \gg 2$ (as in all nine models tested; Table~\ref{tab:frontier-scb}) signals that extraction amplifies rather than checks the model's prior. Report as mean $\pm$ bootstrap 95\% CI.
1498	\emph{Effective-K} ($K_\text{eff}$; Eq.~\ref{eq:effk}): compute Fleiss' $\kappa$ across $K$ traces, then $K_\text{eff} = 1 + (K-1)(1-\kappa)$. Threshold: $K_\text{eff} \leq 1.30$ never improves in our experiments---aggregation collapses to majority voting. $K_\text{eff} > 1.8$ is a necessary (not sufficient) condition for gain.
1499	\emph{Degenerate Consensus} ($C_0$; \S\ref{sec:condorcet}): the fraction of problems where all $K$ traces agree. $C_0 > 95\%$ renders aggregation moot; $C_0 < 5\%$ means the model is maximally uncertain and constraints tend to amplify noise.
1500	\emph{ProcessSim} (Eq.~\ref{eq:process-sim}): mean pairwise cosine similarity of TF-IDF trace vectors. $\text{ProcessSim} > 0.6$ indicates homogeneous reasoning; combined with $\text{BR} > 2$, this predicts SCB will dominate.
1501	A practitioner should compute all four on a held-out sample ($n \geq 50$). If $K_\text{eff} \leq 1.30$ or $C_0 > 95\%$ or ($\text{BR} > 2$ and $\text{ProcessSim} > 0.6$), symbolic self-verification is unlikely to help.
1502	
1503	\paragraph{BR permutation null model.}
1504	\label{app:br-permutation}
1505	The permutation test referenced in \S\ref{sec:confirmation-bias} proceeds as follows:
1506	\begin{enumerate}[nosep,leftmargin=*]
1507	\item For each problem $p$ with extracted constraints $\{c_1, \ldots, c_M\}$ and source answers $\{a_1, \ldots, a_M\}$:
1508	\item Randomly permute constraint-to-answer assignments within $p$ (preserving per-trace constraint counts).
1509	\item Compute $\text{BR}_\text{null}$ from the permuted assignments.
1510	\item Repeat $10{,}000$ times to obtain the null distribution.
1511	\item Compute $p$-value $= |\{r : \text{BR}_\text{null}^{(r)} \geq \text{BR}_\text{obs}\}| / 10{,}000$.
1512	\end{enumerate}
1513	Across all tested conditions, $\text{BR}_\text{null} \approx \text{BR}_\text{obs}$ ($p > 0.7$), confirming that the observed bias ratio is fully explained by trace-count geometry under source-attribution scoring (Observation~1), not by an independent extraction bias.
1514	
1515	\paragraph{Future directions: trained extractors and beyond.}
1516	\label{app:future-directions}
1517	Our oracle controls reveal that perfect extraction would yield $+29.90$\,pp over SC on Mistral-7B FOLIO---self-extraction captures only ${\sim}12\%$ of this ceiling. This gap motivates several future directions.
1518	\emph{Trained constraint extractors}: fine-tuning a small model (e.g., encoder-only) on human-annotated FOL from logic benchmarks could produce genuinely discriminative constraints that break the distributional prior. The key design constraint is structural independence---the extractor should not share training data or architecture with the generator, mirroring the cross-architecture NLI escape (\S\ref{sec:cross-arch}).
1519	\emph{Multi-model ensembles}: rather than single cross-architecture pairs, combining $M$ structurally independent verifiers could further reduce correlated errors. The capability-gap condition (\S\ref{sec:cross-arch}) predicts that each verifier must exceed the generator on the target task to contribute positively; empirical verification across heterogeneous verifier pools is needed.
1520	\emph{External knowledge grounding}: connecting to knowledge bases (Wikidata, domain ontologies) could inject verification signal absent from any model's parameters. This avoids SCB entirely by grounding constraints in external facts rather than self-generated traces.
1521	\emph{SCB-aware aggregation}: current MAX-SAT aggregation treats all constraints equally. Weighting constraints by estimated independence (e.g., inverse ProcessSim with other traces' constraints) or by discriminative power (e.g., cross-validation on held-out traces) could partially mitigate SCB without requiring external verifiers.
1522	
1523	\paragraph{SCB as an evaluation framework.}
1524	\label{app:scb-evaluation}
1525	The SCB metrics---BR, $K_\text{eff}$, ProcessSim, and CCR---can serve as a general evaluation framework for self-improvement methods beyond SICA. Any method that extracts structured representations from a model's own outputs (self-verification \citep{huang2024selfcorrect}, self-refinement \citep{madaan2023selfrefine}, chain-of-verification \citep{dhuliawala2023chainofverification}, self-consistency \citep{wang2023sc}) faces the distributional prior that generates SCB. We propose that future work on self-improvement methods report: (1)~BR on error cases (does the method's verification signal correlate with the model's majority answer, or does it provide independent information?); (2)~$K_\text{eff}$ or an analogous diversity metric (does the method generate genuinely diverse candidates, or does it amplify a single mode?); (3)~CCR (does the method preferentially correct errors, or does it preferentially confirm them?). A method with $\text{BR} < 1$, high $K_\text{eff}$, and $\text{CCR} > 0$ demonstrates genuine self-improvement; $\text{BR} > 1$ with $\text{CCR} < 0$ indicates that the method suffers from SCB regardless of aggregate accuracy gains, which may reflect favorable base rates rather than corrective signal.
1526	
1527	\paragraph{Additional scope considerations.}
1528	
1529	Beyond the limitations discussed in the main text, several additional constraints bound our conclusions. Seven of our eleven model-domain conditions have $n \leq 60$, providing insufficient statistical power for confirmatory claims; power analysis shows that the minimum detectable effect exceeds 5\,pp for these conditions (Table~\ref{tab:power}), so they serve as regime characterization rather than definitive tests. Our extraction prompts use a single zero-shot template per domain; alternative prompting strategies (few-shot exemplars, chain-of-thought extraction, or iterative refinement) might yield higher-quality constraints, though the oracle gap suggests the bottleneck is structural rather than prompt-specific. The constraint quality analysis (91.8\% discriminative rate, 39.2\% source-trace minority weight) covers Qwen2.5-14B on FOLIO + ProofWriter ($N = 804$); other model-domain combinations may exhibit different characteristics. Constraint extraction uses $T_{\text{ext}} = 0.3$ while trace sampling uses $T = 0.7$; alternative extraction temperatures might yield different results. Although we prompt for first-order logic formalizations, 99.0\% of extracted constraints are propositional at the Z3 level, with only 1.0\% using true quantifiers ($\forall$/$\exists$); whether models capable of genuine quantified reasoning would yield higher discriminative rates is untested. Deduplication uses syntactic equivalence (global average dedup ratio: 46.0\%), so semantically equivalent constraints with different surface forms receive separate weights; Z3-based semantic deduplication removes an additional ${\sim}$10\% of constraints and yields a small but significant improvement over no deduplication ($p = 0.013$), suggesting room for better dedup strategies. The GSM8K pilot ($n = 30$) illustrates the constraint-absent regime and should not be interpreted as confirmatory evidence.
1530	
1531	\section{Use of AI Assistants}
1532	\label{app:ai-assistants}
1533	
1534	We used Claude (Anthropic) as an AI coding and writing assistant
1535	throughout this work. Specifically:
1536	\begin{itemize}
1537	    \item \textbf{Code:} drafting experiment scripts, data-processing
1538	    pipelines, and analysis utilities; debugging and refactoring.
1539	    \item \textbf{Writing:} drafting and revising paper sections,
1540	    polishing prose, and reformatting LaTeX.
1541	    \item \textbf{Literature:} summarizing related papers to inform
1542	    the related-work section.
1543	\end{itemize}
1544	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3ed49da8-9ed0-4cef-9e31-985de818400f",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "01a4ab5e-4d7b-4cac-8270-5a5e3809c892",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
      "content": "$0.3^\\dagger$ & 59.31 & $+$3.43 & 68.8 \\\\\n0.5 & 56.37 & $+$0.49 & 68.2 \\\\\n0.7 & 53.43 & $-$2.45 & 67.3 \\\\\n1.0 & 55.39 & $-$0.49 & 65.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nControlling for the trace set (excluding $T_{\\text{ext}} = 0.3$, which uses a different seed), all conditions yield $\\Delta \\leq +1.47$\\,pp (n.s.), indicating that extraction temperature has no significant effect on SICA accuracy. This supports the structural nature of symbolic confirmation bias: the bottleneck is what gets extracted, not the temperature at which extraction occurs.\n\n\\paragraph{Multi-seed replication.}\n\\label{app:multi-seed}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Multi-seed replication results across four model$\\times$dataset conditions. Each row uses an independent seed with fresh traces ($K{=}12$, $T{=}0.7$). Mistral-7B$\\times$FOLIO shows directionally unstable $\\Delta$ ($+0.16 \\pm 2.70$\\,pp); all ProofWriter conditions show consistently negative $\\Delta$ across all seeds ($p < .001$ for LLaMA-8B and Mistral-7B). Qwen3-14B results pending.}\n\\label{tab:multi-seed}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lrrrr@{}}\n\\toprule\nSeed & SC (\\%) & SICA (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\n\\multicolumn{4}{@{}l}{\\textit{Mistral-7B $\\times$ FOLIO ($n{=}204$)\\textsuperscript{a}}} \\\\\n123 & 54.41 & 57.35 & $+$2.94 \\\\\n456 & 55.88 & 55.88 & 0.00 \\\\\n789 & 59.31 & 56.86 & $-$2.45 \\\\\n\\midrule\nMean $\\pm$ SD & 56.53 $\\pm$ 2.51 & 56.70 $\\pm$ 0.75 & $+$0.16 $\\pm$ 2.70 \\\\\n\\midrule\n\\multicolumn{4}{@{}l}{\\textit{Qwen2.5-14B $\\times$ FOLIO ($n{=}204$)}} \\\\\n42 & 77.50 & 75.49 & $-$2.01 \\\\\n123 & 74.51 & 73.04 & $-$1.47 \\\\\n456 & 74.02 & 74.02 & 0.00 \\\\\n789 & 74.02 & 72.55 & $-$1.47 \\\\\n\\midrule\nMean $\\pm$ SD & 75.01 $\\pm$ 1.67 & 73.78 $\\pm$ 1.30 & $-$1.24 $\\pm$ 0.86 \\\\\n\\midrule\n\\multicolumn{4}{@{}l}{\\textit{Mistral-7B $\\times$ ProofWriter ($n{=}600$)}} \\\\\n42  & 39.33 & 36.50 & $-$2.83 \\\\\n123 & 40.83 & 37.50 & $-$3.33 \\\\\n456 & 39.83 & 38.50 & $-$1.33 \\\\\n789 & 38.83 & 37.17 & $-$1.67 \\\\\n\\midrule\nMean $\\pm$ SD & 39.70 $\\pm$ 0.85 & 37.42 $\\pm$ 0.83 & $-$2.29 $\\pm$ 0.95 \\\\\n\\midrule\n\\multicolumn{4}{@{}l}{\\textit{LLaMA-3.1-8B $\\times$ ProofWriter ($n{=}600$)}} \\\\\n42  & 72.50 & 65.00 & $-$7.50 \\\\\n123 & 71.33 & 64.00 & $-$7.33 \\\\\n456 & 71.67 & 66.17 & $-$5.50 \\\\\n789 & 71.17 & 66.50 & $-$4.67 \\\\\n\\midrule\nMean $\\pm$ SD & 71.67 $\\pm$ 0.59 & 65.42 $\\pm$ 1.14 & $-$6.25 $\\pm$ 1.34 \\\\\n\\bottomrule\n\\end{tabular}}\n\\vspace{2pt}\n{\\footnotesize \\textsuperscript{a}Original baseline (exp033) used no fixed seed and is excluded from seed statistics.}\n\\end{table}\n\nOn ProofWriter, all eight Mistral-7B and LLaMA-8B seeds yield negative $\\Delta$ (range $-1.33$ to $-7.50$\\,pp), with all LLaMA-8B McNemar tests reaching $p < .001$. The consistency across seeds confirms that negative $\\Delta$ on ProofWriter is not an artifact of any single random sample.\n\n\\subsection{Sub-population Analysis}\n\\label{app:subpopulation}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{SICA vs.\\ SC accuracy by gold-label type (Mistral-7B). Corrected SC baseline uses alphabetical tiebreaking. $\\Delta$\\,pp = SICA $-$ SC. $p$-values from exact McNemar test (two-sided).}\n\\label{tab:subpop-answer-type}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{ll rrr rr}\n\\toprule\n\\textbf{Dataset} & \\textbf{Label} & $n$ & \\textbf{SC} & \\textbf{SICA} & $\\Delta$\\,pp & $p$ \\\\\n\\midrule\n\\multirow{4}{*}{FOLIO-204}\n & True    &  72 & 56.9 & 62.5 & $+$5.6 & .125 \\\\\n & False   &  63 & 42.9 & 42.9 & $\\pm$0.0 & 1.0\\hphantom{00} \\\\\n & Unknown &  69 & 66.7 & 71.0 & $+$4.3 & .250 \\\\\n & \\textit{Overall} & 204 & 55.9 & 59.3 & $+$3.4 & .092 \\\\\n\\midrule\n\\multirow{4}{*}{PW-600}\n & True    & 200 &  8.5 &  6.0 & $-$2.5 & .063 \\\\\n & False   & 200 & 19.5 & 14.5 & $-$5.0 & .076 \\\\\n & Unknown & 200 & 90.0 & 89.0 & $-$1.0 & .774 \\\\\n & \\textit{Overall} & 600 & 39.3 & 36.5 & $-$2.8 & .014\\rlap{*} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{SICA vs.\\ SC accuracy by extracted constraint count tertile (Mistral-7B). Corrected SC baseline (alphabetical tiebreaking). Constraint counts are unique deduplicated constraints per problem.}\n\\label{tab:subpop-constraint}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{ll rr rrr rr}\n\\toprule\n\\textbf{Dataset} & \\textbf{Tertile} & $n$ & $\\bar{c}$ & \\textbf{SC} & \\textbf{SICA} & $\\Delta$\\,pp & $p$ \\\\\n\\midrule\n\\multirow{3}{*}{FOLIO-204}\n & Low \\scriptsize{[0--32]}   &  74 & 21.7 & 62.2 & 63.5 & $+$1.4 & 1.0\\hphantom{00} \\\\\n & Mid \\scriptsize{[33--47]}  &  64 & 39.7 & 50.0 & 59.4 & $+$9.4 & .031\\rlap{*} \\\\\n & High \\scriptsize{[48--83]} &  66 & 58.7 & 54.5 & 54.5 & $\\pm$0.0 & 1.0\\hphantom{00} \\\\\n\\midrule\n\\multirow{3}{*}{PW-600}\n & Low \\scriptsize{[0--39]}   & 212 & 28.8 & 43.9 & 39.6 & $-$4.3 & .078 \\\\\n & Mid \\scriptsize{[40--52]}  & 196 & 45.8 & 40.8 & 37.2 & $-$3.6 & .143 \\\\\n & High \\scriptsize{[53--99]} & 192 & 63.7 & 32.8 & 32.3 & $-$0.5 & 1.0\\hphantom{00} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nOn FOLIO-204 with the corrected SC baseline (alphabetical tiebreaking), SICA improves over SC by $+$3.4\\,pp overall (55.9\\% $\\to$ 59.3\\%), though the aggregate McNemar test is marginally non-significant ($p{=}.092$).\nThe gain concentrates in the mid-constraint tertile ($+$9.4\\,pp, $p{=}.031$), where sufficient symbolic evidence exists for MaxSAT to meaningfully re-rank answers; in the low- and high-constraint groups the methods perform comparably.\nOn ProofWriter-600, SICA shows a small uniform degradation consistent with the main results, attenuating in the high-constraint tertile ($\\Delta{=}{-}0.5$\\,pp, $p{=}1.0$).\nWe note that with six subgroup tests, one significant result at $\\alpha{=}0.05$ is expected by chance; the mid-constraint finding should be interpreted as exploratory.\n\n\\paragraph{Individual intervention significance.}\n\\label{app:intervention-individual}\nOf the 27 training-free remediation strategies (Figure~\\ref{fig:interventions-summary}), the two largest positive effects are Cross-model Qwen3$\\to$Mistral ($+0.98$\\,pp) and Generational ($+0.49$\\,pp); neither approaches statistical significance ($p > 0.5$ for both). The largest negative effects are LLM-Debate ($-18.6$\\,pp, $p < 0.001$) and Contrastive Scoring ($-9.3$\\,pp, $p < 0.001$). After BH correction across all 27 comparisons, only these two negative results remain significant. No strategy produces a significant positive effect under any correction procedure.\n\n\\section{Extended Discussion}\n\\label{app:extended-discussion}\n\\label{app:limitations-extended}\n\n\\paragraph{SCB versus CoT unfaithfulness.}\nSCB is distinct from CoT unfaithfulness \\citep{turpin2023language} and CoT-level confirmation bias \\citep{wan2025unveiling, jhaveri2026failing}. CoT unfaithfulness concerns whether stated reasoning reflects actual computation; SCB concerns whether \\emph{self-extracted formal constraints} mirror the model's answer distribution. Even if traces were perfectly faithful, self-extraction would still inherit the distributional bias---the constraint $P(\\text{answer\\_A})$ reflects vote share, not logical validity. The shuffle control (\\S\\ref{sec:confirmation-bias}) confirms this: randomizing constraint--answer associations preserves BR, showing the bias is in the trace-count distribution, not in extraction-specific errors. However, if traces are unfaithful, the mirage may be worse than our measurements suggest, because constraints would reflect not the model's reasoning but its post-hoc rationalization.\n\n\\paragraph{Implications for neuro-symbolic practitioners.}\nOur results do not imply that neuro-symbolic methods are inherently flawed---they imply that \\emph{self-extracted} constraints cannot provide independent verification. The key distinction is \\emph{when} formalization occurs relative to answer generation. Specification-generation approaches (e.g., SatLM \\citep{ye2024satlm}, Logic-LM \\citep{pan2023logiclm}) formalize the problem \\emph{before} generating candidate answers, avoiding the extraction bottleneck; SatLM's success confirms that the formal verification mechanism is sound when constraints are independently derived. Trace-extraction (this work) operates post-hoc on reasoning traces that already contain candidates, inheriting the distributional prior that generates SCB. When post-hoc verification is unavoidable, practitioners should employ external verifiers from a different architecture family (\\S\\ref{sec:cross-arch}) and use the diagnostic framework in \\S\\ref{sec:discussion} to assess feasibility before deployment. The SCB diagnostic toolkit (below) provides detailed computation methods and threshold recommendations.\n\n\\paragraph{Test-time scaling implications.}\nVote diversity decreases with model capability: $K_\\text{eff}$ drops from 3.62 (Mistral-7B on ProofWriter) to 1.09 (Qwen3-14B thinking mode). This creates a fundamental tension for o1/R1-style scaling \\citep{guo2025deepseekr1}: longer reasoning chains produce more coherent but less diverse traces, reducing the marginal value of additional samples. Our Process-$\\kappa$ analysis (\\S\\ref{sec:process-kappa}) reveals that this homogenization operates at the reasoning-process level, not just answer level---traces that disagree on final answers still share 69\\% of their reasoning structure. Cross-architecture ensembles offer a path forward, but the capability-gap condition (\\S\\ref{sec:cross-arch}) implies that the verifier must be genuinely complementary, not just different.\n\n\\paragraph{SCB diagnostic toolkit.}\n\\label{app:diagnostic-toolkit}\nWe recommend four zero-cost diagnostics, computable from sampled traces alone, to predict whether symbolic self-verification will help or hurt before deployment.\n\\emph{Bias Ratio} (BR; \\S\\ref{sec:confirmation-bias}): for each problem, compute the fraction of constraints supporting the majority answer, divided by majority vote share. $\\text{BR} > 1$ indicates constraints are biased toward the majority; $\\text{BR} \\gg 2$ (as in all nine models tested; Table~\\ref{tab:frontier-scb}) signals that extraction amplifies rather than checks the model's prior. Report as mean $\\pm$ bootstrap 95\\% CI.\n\\emph{Effective-K} ($K_\\text{eff}$; Eq.~\\ref{eq:effk}): compute Fleiss' $\\kappa$ across $K$ traces, then $K_\\text{eff} = 1 + (K-1)(1-\\kappa)$. Threshold: $K_\\text{eff} \\leq 1.30$ never improves in our experiments---aggregation collapses to majority voting. $K_\\text{eff} > 1.8$ is a necessary (not sufficient) condition for gain.\n\\emph{Degenerate Consensus} ($C_0$; \\S\\ref{sec:condorcet}): the fraction of problems where all $K$ traces agree. $C_0 > 95\\%$ renders aggregation moot; $C_0 < 5\\%$ means the model is maximally uncertain and constraints tend to amplify noise.\n\\emph{ProcessSim} (Eq.~\\ref{eq:process-sim}): mean pairwise cosine similarity of TF-IDF trace vectors. $\\text{ProcessSim} > 0.6$ indicates homogeneous reasoning; combined with $\\text{BR} > 2$, this predicts SCB will dominate.\nA practitioner should compute all four on a held-out sample ($n \\geq 50$). If $K_\\text{eff} \\leq 1.30$ or $C_0 > 95\\%$ or ($\\text{BR} > 2$ and $\\text{ProcessSim} > 0.6$), symbolic self-verification is unlikely to help.\n\n\\paragraph{BR permutation null model.}\n\\label{app:br-permutation}\nThe permutation test referenced in \\S\\ref{sec:confirmation-bias} proceeds as follows:\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item For each problem $p$ with extracted constraints $\\{c_1, \\ldots, c_M\\}$ and source answers $\\{a_1, \\ldots, a_M\\}$:\n\\item Randomly permute constraint-to-answer assignments within $p$ (preserving per-trace constraint counts).\n\\item Compute $\\text{BR}_\\text{null}$ from the permuted assignments.\n\\item Repeat $10{,}000$ times to obtain the null distribution.\n\\item Compute $p$-value $= |\\{r : \\text{BR}_\\text{null}^{(r)} \\geq \\text{BR}_\\text{obs}\\}| / 10{,}000$.\n\\end{enumerate}\nAcross all tested conditions, $\\text{BR}_\\text{null} \\approx \\text{BR}_\\text{obs}$ ($p > 0.7$), confirming that the observed bias ratio is fully explained by trace-count geometry under source-attribution scoring (Observation~1), not by an independent extraction bias.\n\n\\paragraph{Future directions: trained extractors and beyond.}\n\\label{app:future-directions}\nOur oracle controls reveal that perfect extraction would yield $+29.90$\\,pp over SC on Mistral-7B FOLIO---self-extraction captures only ${\\sim}12\\%$ of this ceiling. This gap motivates several future directions.\n\\emph{Trained constraint extractors}: fine-tuning a small model (e.g., encoder-only) on human-annotated FOL from logic benchmarks could produce genuinely discriminative constraints that break the distributional prior. The key design constraint is structural independence---the extractor should not share training data or architecture with the generator, mirroring the cross-architecture NLI escape (\\S\\ref{sec:cross-arch}).\n\\emph{Multi-model ensembles}: rather than single cross-architecture pairs, combining $M$ structurally independent verifiers could further reduce correlated errors. The capability-gap condition (\\S\\ref{sec:cross-arch}) predicts that each verifier must exceed the generator on the target task to contribute positively; empirical verification across heterogeneous verifier pools is needed.\n\\emph{External knowledge grounding}: connecting to knowledge bases (Wikidata, domain ontologies) could inject verification signal absent from any model's parameters. This avoids SCB entirely by grounding constraints in external facts rather than self-generated traces.\n\\emph{SCB-aware aggregation}: current MAX-SAT aggregation treats all constraints equally. Weighting constraints by estimated independence (e.g., inverse ProcessSim with other traces' constraints) or by discriminative power (e.g., cross-validation on held-out traces) could partially mitigate SCB without requiring external verifiers.\n\n\\paragraph{SCB as an evaluation framework.}\n\\label{app:scb-evaluation}\nThe SCB metrics---BR, $K_\\text{eff}$, ProcessSim, and CCR---can serve as a general evaluation framework for self-improvement methods beyond SICA. Any method that extracts structured representations from a model's own outputs (self-verification \\citep{huang2024selfcorrect}, self-refinement \\citep{madaan2023selfrefine}, chain-of-verification \\citep{dhuliawala2023chainofverification}, self-consistency \\citep{wang2023sc}) faces the distributional prior that generates SCB. We propose that future work on self-improvement methods report: (1)~BR on error cases (does the method's verification signal correlate with the model's majority answer, or does it provide independent information?); (2)~$K_\\text{eff}$ or an analogous diversity metric (does the method generate genuinely diverse candidates, or does it amplify a single mode?); (3)~CCR (does the method preferentially correct errors, or does it preferentially confirm them?). A method with $\\text{BR} < 1$, high $K_\\text{eff}$, and $\\text{CCR} > 0$ demonstrates genuine self-improvement; $\\text{BR} > 1$ with $\\text{CCR} < 0$ indicates that the method suffers from SCB regardless of aggregate accuracy gains, which may reflect favorable base rates rather than corrective signal.\n\n\\paragraph{Additional scope considerations.}\n\nBeyond the limitations discussed in the main text, several additional constraints bound our conclusions. Seven of our eleven model-domain conditions have $n \\leq 60$, providing insufficient statistical power for confirmatory claims; power analysis shows that the minimum detectable effect exceeds 5\\,pp for these conditions (Table~\\ref{tab:power}), so they serve as regime characterization rather than definitive tests. Our extraction prompts use a single zero-shot template per domain; alternative prompting strategies (few-shot exemplars, chain-of-thought extraction, or iterative refinement) might yield higher-quality constraints, though the oracle gap suggests the bottleneck is structural rather than prompt-specific. The constraint quality analysis (91.8\\% discriminative rate, 39.2\\% source-trace minority weight) covers Qwen2.5-14B on FOLIO + ProofWriter ($N = 804$); other model-domain combinations may exhibit different characteristics. Constraint extraction uses $T_{\\text{ext}} = 0.3$ while trace sampling uses $T = 0.7$; alternative extraction temperatures might yield different results. Although we prompt for first-order logic formalizations, 99.0\\% of extracted constraints are propositional at the Z3 level, with only 1.0\\% using true quantifiers ($\\forall$/$\\exists$); whether models capable of genuine quantified reasoning would yield higher discriminative rates is untested. Deduplication uses syntactic equivalence (global average dedup ratio: 46.0\\%), so semantically equivalent constraints with different surface forms receive separate weights; Z3-based semantic deduplication removes an additional ${\\sim}$10\\% of constraints and yields a small but significant improvement over no deduplication ($p = 0.013$), suggesting room for better dedup strategies. The GSM8K pilot ($n = 30$) illustrates the constraint-absent regime and should not be interpreted as confirmatory evidence.\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    the related-work section.\n\\end{itemize}\n",
      "numLines": 185,
      "startLine": 1360,
      "totalLines": 1544
    }
  },
  "sourceToolAssistantUUID": "3ed49da8-9ed0-4cef-9e31-985de818400f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 77 · 2026-05-24T04:29:45.641Z_

<details open><summary>🔧 Tool call — Bash · `toolu_012SQDntUW5nPMhCFCDG8qDg`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = data['result']\nparsed = json.loads(result)\nexperiments = parsed['data']['experiments']\n\n# Get more experiments with metrics\nfor exp_id, exp in experiments.items():\n    metrics = exp.get('metrics', {})\n    if metrics:\n        # Skip already printed ones\n        continue\n    # Print experiments with conclusion field\n    conclusion = exp.get('conclusion', '')\n    notes = exp.get('notes', '')\n    if 'qwen3' in exp_id.lower() or 'seed42' in exp_id.lower() or 'canonical' in exp_id.lower() or 'main' in exp_id.lower():\n        print(f'=== {exp_id} ===')\n        print(f'  status: {exp.get(\\\"status\\\", \\\"?\\\")}')\n        print(f'  hypothesis: {exp.get(\\\"hypothesis\\\", \\\"?\\\")[:200]}')\n        if metrics:\n            for k, v in metrics.items():\n                print(f'  {k}: {v}')\n        if conclusion:\n            print(f'  conclusion: {conclusion}')\n        if notes:\n            print(f'  notes: {notes[:200]}')\n        print()\n\" 2>&1 | head -100",
  "description": "Find Qwen3 and canonical experiments",
  "timeout": 15000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "01a4ab5e-4d7b-4cac-8270-5a5e3809c892",
  "isSidechain": false,
  "requestId": "req_011CbLmGu2Te5936NhsEav49",
  "type": "assistant",
  "uuid": "b55fdb6c-944b-46fe-b4ad-14e215c5b263",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015oFprcWwB8aY5H34fZibnN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8277,
      "cache_read_input_tokens": 84984,
      "output_tokens": 1190,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8277,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1190,
          "cache_read_input_tokens": 84984,
          "cache_creation_input_tokens": 8277,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8277
          },
          "type": "message"
        }
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

_source line 78 · 2026-05-24T04:29:45.779Z_

<details><summary>↩ Tool result · `toolu_012SQDntUW5nPMhCFCDG8qDg`</summary>

```text
=== exp-multi-seed-qwen3-pw-seed789 ===
  status: RUNNING
  hypothesis: Qwen3-14B non-thinking PW seed789 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。

=== exp-multi-seed-qwen3-pw-seed456 ===
  status: RUNNING
  hypothesis: Qwen3-14B non-thinking PW seed456 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。

=== exp-multi-seed-qwen3-pw-seed123 ===
  status: RUNNING
  hypothesis: Qwen3-14B non-thinking PW seed123 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。

=== exp-028b-qwen3-thinking-folio204 ===
  status: DONE
  hypothesis: Qwen3-14B thinking mode (enable_thinking=True, 32K context) 在 FOLIO-204 上 SICA vs SC。D028 pilot (35/204, delta=+2.86pp) 被 kill。thinking mode 产生更 diverse+higher-quality reasoning traces，如果同时提升 trace qu
  conclusion: killed
  notes: 失败根因：exp-058 部署到 cuda:3+port:8003 覆盖了 exp-028b 的 vLLM（非 OOM）。166/204 已完成，intermediates 完整保存。支持 resume（仅需 38 题 ~90min），但需等 exp-058 完成释放 cuda:3。

=== exp-028-qwen3-14b-thinking ===
  status: DONE
  hypothesis: Qwen3-14B thinking mode 在 FOLIO 204 上 SICA vs SC：原生推理能力（内置 CoT）是否改变 capability trap？两种可能：(a) thinking mode 使 traces 更确定性（类似 QwQ-32B），C0 极低→SICA≡SC；(b) thinking mode 提升 constraint extraction 质量，打破 capa
  conclusion: killed
  notes: Killed per D049: extraction_rate 73% below 80% threshold. Partial results (35/204): SICA 88.57%, SC 85.71%, delta +2.86pp. But extraction_rate degrading and ETA 16h+ made continued run not worthwhile.

=== exp-033-qwen3-pw600-nonthinking ===
  status: DONE
  hypothesis: Qwen3-14B in non-thinking mode on ProofWriter 600 will show whether SICA's constraint-based consensus improves over SC@K for a model without chain-of-thought reasoning overhead, providing a controlled
  conclusion: failed
  notes: FAILED: AutoDL 平台级 SIGTERM 导致 vLLM EngineCore 崩溃 (00:05:54)，后紧急清理 Worker 误杀 tmux server 连带终止。518/600 intermediates 有效可恢复。
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b55fdb6c-944b-46fe-b4ad-14e215c5b263",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "1f1453aa-acdf-4539-8eea-c2c9d6f24a1a",
  "toolUseResult": {
    "stdout": "=== exp-multi-seed-qwen3-pw-seed789 ===\n  status: RUNNING\n  hypothesis: Qwen3-14B non-thinking PW seed789 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。\n\n=== exp-multi-seed-qwen3-pw-seed456 ===\n  status: RUNNING\n  hypothesis: Qwen3-14B non-thinking PW seed456 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。\n\n=== exp-multi-seed-qwen3-pw-seed123 ===\n  status: RUNNING\n  hypothesis: Qwen3-14B non-thinking PW seed123 多种子复制。验证 SCB 在 ProofWriter 上跨 seed 稳定性（Δ(SICA-SC)≤0）。配合 seed42 组成多 seed 覆盖。\n\n=== exp-028b-qwen3-thinking-folio204 ===\n  status: DONE\n  hypothesis: Qwen3-14B thinking mode (enable_thinking=True, 32K context) 在 FOLIO-204 上 SICA vs SC。D028 pilot (35/204, delta=+2.86pp) 被 kill。thinking mode 产生更 diverse+higher-quality reasoning traces，如果同时提升 trace qu\n  conclusion: killed\n  notes: 失败根因：exp-058 部署到 cuda:3+port:8003 覆盖了 exp-028b 的 vLLM（非 OOM）。166/204 已完成，intermediates 完整保存。支持 resume（仅需 38 题 ~90min），但需等 exp-058 完成释放 cuda:3。\n\n=== exp-028-qwen3-14b-thinking ===\n  status: DONE\n  hypothesis: Qwen3-14B thinking mode 在 FOLIO 204 上 SICA vs SC：原生推理能力（内置 CoT）是否改变 capability trap？两种可能：(a) thinking mode 使 traces 更确定性（类似 QwQ-32B），C0 极低→SICA≡SC；(b) thinking mode 提升 constraint extraction 质量，打破 capa\n  conclusion: killed\n  notes: Killed per D049: extraction_rate 73% below 80% threshold. Partial results (35/204): SICA 88.57%, SC 85.71%, delta +2.86pp. But extraction_rate degrading and ETA 16h+ made continued run not worthwhile.\n\n=== exp-033-qwen3-pw600-nonthinking ===\n  status: DONE\n  hypothesis: Qwen3-14B in non-thinking mode on ProofWriter 600 will show whether SICA's constraint-based consensus improves over SC@K for a model without chain-of-thought reasoning overhead, providing a controlled\n  conclusion: failed\n  notes: FAILED: AutoDL 平台级 SIGTERM 导致 vLLM EngineCore 崩溃 (00:05:54)，后紧急清理 Worker 误杀 tmux server 连带终止。518/600 intermediates 有效可恢复。",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "b55fdb6c-944b-46fe-b4ad-14e215c5b263",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 79 · 2026-05-24T04:29:50.772Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01CqLu1nsqWWgxR6auxfyUNf`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/f7fd8db5-5343-4e73-85aa-00068ad076e9/tool-results/mcp-agent-ml-research-read_registry-1779596909608.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = data['result']\nparsed = json.loads(result)\nexperiments = parsed['data']['experiments']\n\n# Find experiments related to key results\nkey_terms = ['qwen3', 'o3', 'gpt4o', 'gpt-4o', 'gemini', 'deberta-ft', 'finetuned', 'nli-combo', 'cross-generator', 'llama-pw-seed', 'mistral-pw-seed', 'qwen25-pw-seed']\nfor exp_id, exp in experiments.items():\n    if any(term in exp_id.lower() for term in key_terms):\n        metrics = exp.get('metrics', {})\n        if metrics:\n            print(f'=== {exp_id} ===')\n            print(f'  status: {exp.get(\\\"status\\\", \\\"?\\\")}')\n            for k, v in metrics.items():\n                if isinstance(v, dict):\n                    print(f'  {k}: {json.dumps(v, ensure_ascii=False)[:200]}')\n                else:\n                    print(f'  {k}: {v}')\n            print()\n\" 2>&1 | head -200",
  "description": "Extract key experiment metrics from registry",
  "timeout": 15000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1f1453aa-acdf-4539-8eea-c2c9d6f24a1a",
  "isSidechain": false,
  "requestId": "req_011CbLmGu2Te5936NhsEav49",
  "type": "assistant",
  "uuid": "50901569-43c2-4637-a5d6-619c252dcfd4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015oFprcWwB8aY5H34fZibnN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8277,
      "cache_read_input_tokens": 84984,
      "output_tokens": 1190,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8277,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1190,
          "cache_read_input_tokens": 84984,
          "cache_creation_input_tokens": 8277,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8277
          },
          "type": "message"
        }
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

_source line 80 · 2026-05-24T04:29:50.883Z_

<details><summary>↩ Tool result · `toolu_01CqLu1nsqWWgxR6auxfyUNf`</summary>

```text
=== exp-multi-seed-llama-pw-seed456-v2 ===
  status: DONE
  sc_accuracy: 71.67
  sica_accuracy: 66.17
  delta: -5.5
  n: 600

=== exp-092-llama8b-pw-nli-combo ===
  status: DONE
  n: 600
  sc_accuracy: 0.7
  nli_standalone: 0.55
  capability_gap_pp: -15
  combo_w1: 0.7283
  combo_w3: 0.7417
  combo_w5: 0.7167
  delta_w1_pp: 2.83
  delta_w3_pp: 4.17
  delta_w5_pp: 1.67
  mcnemar_w1_p: 0.0001
  mcnemar_w3_p: 0.0035
  mcnemar_w5_p: 0.4335
  nli_correct_sc_wrong: 120
  sc_correct_nli_wrong: 210

=== exp-deberta-ft-combo ===
  status: PREPARING
  standalone_acc: 99.67
  standalone_n: 600
  errors: 2
  d061_corrected: True
  mistral: {"sc_baseline": 39.17, "w1": {"acc": 42.33, "delta": 3.17, "p": "<0.0001"}, "w3": {"acc": 52.17, "delta": 13, "p": "<0.0001"}, "w5": {"acc": 65.5, "delta": 26.33, "p": "<0.0001"}, "nli_up_sc_down": 36
  llama8b: {"sc_baseline": 72.5, "w1": {"acc": 76, "delta": 3.5, "p": "<0.0001"}, "w3": {"acc": 84.17, "delta": 11.67, "p": "<0.0001"}, "w5": {"acc": 91.67, "delta": 19.17, "p": "<0.0001"}, "nli_up_sc_down": 164
  qwen25_14b: {"sc_baseline": 74, "w1": {"acc": 75, "delta": 1, "p": "<0.05"}, "w3": {"acc": 78.5, "delta": 4.5, "p": "<0.0001"}, "w5": {"acc": 83, "delta": 9, "p": "<0.0001"}}
  qwen3_14b: {"sc_baseline": 85.83, "w1": {"acc": 86.5, "delta": 0.67, "p": "ns"}, "w3": {"acc": 88, "delta": 2.17, "p": "<0.0001"}, "w5": {"acc": 90, "delta": 4.17, "p": "<0.0001"}}

=== exp-091-qwen14b-pw-nli-combo ===
  status: DONE
  n: 600
  sc_accuracy: 0.735
  nli_standalone: 0.55
  capability_gap_pp: -18.5
  combo_w1: 0.7417
  combo_w3: 0.7433
  combo_w5: 0.7533
  delta_w1_pp: 0.67
  delta_w3_pp: 0.83
  delta_w5_pp: 1.83
  mcnemar_w1_p: 0.344
  mcnemar_w3_p: 0.405
  mcnemar_w5_p: 0.144

=== exp-064-deepseek-r1-qwen3-8b-folio204 ===
  status: DONE
  sc_accuracy: 0.8382
  sica_accuracy: 0.8382
  delta: 0
  n_samples: 204
  extraction_rate: 0.3818
  contradiction_rate: 0.0165
  wall_time_min: 355.6

=== exp-068-qwen3-logiqa200 ===
  status: DONE
  sc_accuracy: 0.81
  sica_accuracy: 0.81
  delta: 0
  n_samples: 200

=== exp-059-cross-qwen3-extractor ===
  status: DONE
  n: 204
  cross_sica_accuracy: 0.6029
  orig_sica_accuracy: 0.5931
  sc_accuracy: 0.5588
  delta_cross_vs_sc_pp: 4.41
  delta_cross_vs_orig_pp: 0.98

=== exp-040-qwen3-pw600-16639 ===
  status: DONE
  n: 600
  sc_accuracy: 0.85
  sica_accuracy: 0.8567
  delta_pp: 0.67
  extraction_rate: 0.997
  contradiction_rate: 0.004
  wall_time_min: 1032.2
  failure_type: Type A (confirmation bias)

=== exp-027-qwen3-14b-non-thinking ===
  status: DONE
  n: 204
  k: 12
  sica_accuracy: 0.8431
  sc_accuracy: 0.8382
  delta_pp: 0.49
  extraction_rate: 0.995
  contradiction_rate: 0.0283
  problems_with_contradictions: 69
  total_constraints: 16153
  unique_constraints: 7031
  wall_time_s: 11017
  model: Qwen3-14B
  dataset: FOLIO-204
  mode: non-thinking
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "50901569-43c2-4637-a5d6-619c252dcfd4",
  "isSidechain": false,
  "promptId": "c4aab779-db8b-4460-8f5a-6865ba64ee3c",
  "type": "user",
  "uuid": "0d226e44-25d8-4257-a115-a63e85842403",
  "toolUseResult": {
    "stdout": "=== exp-multi-seed-llama-pw-seed456-v2 ===\n  status: DONE\n  sc_accuracy: 71.67\n  sica_accuracy: 66.17\n  delta: -5.5\n  n: 600\n\n=== exp-092-llama8b-pw-nli-combo ===\n  status: DONE\n  n: 600\n  sc_accuracy: 0.7\n  nli_standalone: 0.55\n  capability_gap_pp: -15\n  combo_w1: 0.7283\n  combo_w3: 0.7417\n  combo_w5: 0.7167\n  delta_w1_pp: 2.83\n  delta_w3_pp: 4.17\n  delta_w5_pp: 1.67\n  mcnemar_w1_p: 0.0001\n  mcnemar_w3_p: 0.0035\n  mcnemar_w5_p: 0.4335\n  nli_correct_sc_wrong: 120\n  sc_correct_nli_wrong: 210\n\n=== exp-deberta-ft-combo ===\n  status: PREPARING\n  standalone_acc: 99.67\n  standalone_n: 600\n  errors: 2\n  d061_corrected: True\n  mistral: {\"sc_baseline\": 39.17, \"w1\": {\"acc\": 42.33, \"delta\": 3.17, \"p\": \"<0.0001\"}, \"w3\": {\"acc\": 52.17, \"delta\": 13, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 65.5, \"delta\": 26.33, \"p\": \"<0.0001\"}, \"nli_up_sc_down\": 36\n  llama8b: {\"sc_baseline\": 72.5, \"w1\": {\"acc\": 76, \"delta\": 3.5, \"p\": \"<0.0001\"}, \"w3\": {\"acc\": 84.17, \"delta\": 11.67, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 91.67, \"delta\": 19.17, \"p\": \"<0.0001\"}, \"nli_up_sc_down\": 164\n  qwen25_14b: {\"sc_baseline\": 74, \"w1\": {\"acc\": 75, \"delta\": 1, \"p\": \"<0.05\"}, \"w3\": {\"acc\": 78.5, \"delta\": 4.5, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 83, \"delta\": 9, \"p\": \"<0.0001\"}}\n  qwen3_14b: {\"sc_baseline\": 85.83, \"w1\": {\"acc\": 86.5, \"delta\": 0.67, \"p\": \"ns\"}, \"w3\": {\"acc\": 88, \"delta\": 2.17, \"p\": \"<0.0001\"}, \"w5\": {\"acc\": 90, \"delta\": 4.17, \"p\": \"<0.0001\"}}\n\n=== exp-091-qwen14b-pw-nli-combo ===\n  status: DONE\n  n: 600\n  sc_accuracy: 0.735\n  nli_standalone: 0.55\n  capability_gap_pp: -18.5\n  combo_w1: 0.7417\n  combo_w3: 0.7433\n  combo_w5: 0.7533\n  delta_w1_pp: 0.67\n  delta_w3_pp: 0.83\n  delta_w5_pp: 1.83\n  mcnemar_w1_p: 0.344\n  mcnemar_w3_p: 0.405\n  mcnemar_w5_p: 0.144\n\n=== exp-064-deepseek-r1-qwen3-8b-folio204 ===\n  status: DONE\n  sc_accuracy: 0.8382\n  sica_accuracy: 0.8382\n  delta: 0\n  n_samples: 204\n  extraction_rate: 0.3818\n  contradiction_rate: 0.0165\n  wall_time_min: 355.6\n\n=== exp-068-qwen3-logiqa200 ===\n  status: DONE\n  sc_accuracy: 0.81\n  sica_accuracy: 0.81\n  delta: 0\n  n_samples: 200\n\n=== exp-059-cross-qwen3-extractor ===\n  status: DONE\n  n: 204\n  cross_sica_accuracy: 0.6029\n  orig_sica_accuracy: 0.5931\n  sc_accuracy: 0.5588\n  delta_cross_vs_sc_pp: 4.41\n  delta_cross_vs_orig_pp: 0.98\n\n=== exp-040-qwen3-pw600-16639 ===\n  status: DONE\n  n: 600\n  sc_accuracy: 0.85\n  sica_accuracy: 0.8567\n  delta_pp: 0.67\n  extraction_rate: 0.997\n  contradiction_rate: 0.004\n  wall_time_min: 1032.2\n  failure_type: Type A (confirmation bias)\n\n=== exp-027-qwen3-14b-non-thinking ===\n  status: DONE\n  n: 204\n  k: 12\n  sica_accuracy: 0.8431\n  sc_accuracy: 0.8382\n  delta_pp: 0.49\n  extraction_rate: 0.995\n  contradiction_rate: 0.0283\n  problems_with_contradictions: 69\n  total_constraints: 16153\n  unique_constraints: 7031\n  wall_time_s: 11017\n  model: Qwen3-14B\n  dataset: FOLIO-204\n  mode: non-thinking",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "50901569-43c2-4637-a5d6-619c252dcfd4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Runtime record

_source line 81_

```json
{
  "type": "last-prompt",
  "leafUuid": "0d226e44-25d8-4257-a115-a63e85842403",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---


### Runtime record

_source line 82_

```json
{
  "type": "ai-title",
  "aiTitle": "Audit paper numerics before submission deadline",
  "sessionId": "f7fd8db5-5343-4e73-85aa-00068ad076e9"
}
```

---

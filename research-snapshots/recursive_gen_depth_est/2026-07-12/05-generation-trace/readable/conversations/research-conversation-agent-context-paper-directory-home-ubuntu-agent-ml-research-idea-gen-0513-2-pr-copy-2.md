# Research conversation: <agent_context> Paper directory: /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/p

**How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 62
- **Recorded user turns:** 1
- **Tool calls:** 18
- **Original source:** `logs/chats/exported-trajectories/account-1/26d975ec-e008-4c6a-b9fc-a4b9bbf1910e.jsonl`
- **Structured JSON:** [`deabc0b236d312a777e7.json`](../../sessions/de/deabc0b236d312a777e7.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-15T15:51:11.371Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-15T15:51:11.371Z",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "content": "&lt;agent_context>\nPaper directory: /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/\nProject: recursive_gen_depth_est\nVenue: EMNLP 2026 ARR May 25\n写作规范: 禁止凭记忆编造引用，所有 bib 条目必须搜索确认。\n&lt;/agent_context>\n\n&lt;project_context>\n# 项目: recursive_gen_depth_est\n\n## 运行环境\n- 服务器名: gpu-6000pro-2\n- SSH 连接命令: ssh connect.westb.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/autodl-tmp/recursive_gen_depth_est\n\n## ⚠️ 活跃约束（必须遵守）\n\n- **C001**: 提交同系列实验（如 DCOL v5/v6）前必须先 read_registry 检查该系列所有历史实验的失败原因和参数约束，确认新 spec 不重复已知错误（原因：DCOL 系列 4 次失败，v4 重复了 v1 完全相同的错误（margin_lr=1e-3 导致 embedding collapse）。Worker 写 spec 时未查阅同系列历史教训。）\n- **C002**: 提交 DCOL 系列新实验前必须先 read_registry 检查同系列所有历史实验的失败原因和参数约束（原因：DCOL v4 重复了 v1 完全相同的错误（margin_lr=1e-3 导致 embedding collapse），系列已连续 4 次失败。Worker 未查阅历史教训直接提交。）\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n你是论文写作 Worker。任务：扩充 bibliography + 术语一致性审查 + orphan bib 清理。\n\n## 目标文件\n- `/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib` — bibliography\n- 所有 .tex 文件在 `/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/` 目录下\n\n## 任务 1: Bibliography 扩充至 25+ refs (R2-N2)\n\n当前 bib 可能不足 25 条。必须覆盖以下领域（Dream D002 硬约束）：\n\n**必须包含的引用**：\n- Watermarking: Kirchenbauer et al. (ICML 2023) \"A Watermark for Large Language Models\"\n- Model collapse theory: Alemohammad et al. (ICLR 2024) \"Self-Consuming Generative Models Go MAD\"; Dohmatob et al. (2024) \"A tale of tails\"; Gerstgrasser et al. (2024) accumulation; Shumailov et al. (Nature 2024) \"AI models collapse\"\n- Data curation: DSIR (Xie et al. 2023), QuRating\n- Multi-source attribution: Uchendu et al. (2020)\n- Binary detectors: Binoculars (Hans et al. ICML 2024), Fast-DetectGPT (Bao et al. 2024), DivEye\n- Decoding strategy effects: Garces Arias et al. (COLING 2025), Holtzman et al. (ICLR 2020) nucleus sampling\n- Detection limits: Sadasivan et al. (2023) paraphrase attack\n- Ordinal methods: CORAL (Cao et al. 2020), CLOC\n- Model collapse + detection: Drayson et al. (EMNLP 2025)\n- EditLens: recent work on editing extent estimation\n- Bakshi et al. (2026): non-monotonic dynamics\n- Marchi et al. (2024): temperature convergence theory\n- Pudasaini et al. (2026): feature fragility under distribution shift\n- Falahati et al. (2026): curated pipelines\n- Sugiyama et al. (2007): covariate shift theory\n- LoRA: Hu et al. (2022)\n\n**方法**: 用 WebSearch 搜索每篇论文获取准确的 bib 信息（作者、标题、venue、年份、页码）。不要凭记忆编造 bib 条目——必须搜索确认。对于 2025-2026 年的论文，搜索时加 \"arxiv\" 或 \"proceedings\" 关键词。\n\n生成标准 BibTeX 格式，key 命名规则：`firstauthor_year_shortname`（如 `kirchenbauer2023watermark`）。\n\n## 任务 2: 术语一致性审查 (R2-W2)\n\n扫描所有 .tex 文件，统一以下术语：\n- \"recursive generation depth\" vs \"generation depth\" vs \"recursive depth\" vs \"iteration depth\" — 统一为 **\"recursive generation depth\"**（首次出现全称，后续可缩写为 \"generation depth\"）\n- \"depth degradation\" vs \"quality degradation\" — 统一\n- \"statistical features\" vs \"hand-crafted features\" vs \"perplexity features\" — 统一措辞\n- \"model collapse\" vs \"recursive collapse\" — 按文献标准用法\n- 确认 EDD 缩写在首次出现时定义\n\n## 任务 3: Orphan bib 清理 (R2-W6)\n\n1. 扫描 references.bib 中所有 bib key\n2. 在所有 .tex 文件中搜索 \\cite{key} 引用\n3. 列出 bib 中存在但正文未引用的 orphan entries\n4. 暂不删除 orphan（可能后续 section 会引用），只在文件末尾用注释标记\n\n## 验证\n完成后统计 bib 条目总数，确认 ≥ 25。列出新增的引用清单。"
}
```

---

### Runtime record

_source line 2 · 2026-05-15T15:51:11.375Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-15T15:51:11.375Z",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

## Round 1

60 recorded events

### User

_source line 3 · 2026-05-15T15:51:11.413Z_

&lt;agent_context>
Paper directory: /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/
Project: recursive_gen_depth_est
Venue: EMNLP 2026 ARR May 25
写作规范: 禁止凭记忆编造引用，所有 bib 条目必须搜索确认。
&lt;/agent_context>

&lt;project_context>
# 项目: recursive_gen_depth_est

## 运行环境
- 服务器名: gpu-6000pro-2
- SSH 连接命令: ssh connect.westb.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/autodl-tmp/recursive_gen_depth_est

## ⚠️ 活跃约束（必须遵守）

- **C001**: 提交同系列实验（如 DCOL v5/v6）前必须先 read_registry 检查该系列所有历史实验的失败原因和参数约束，确认新 spec 不重复已知错误（原因：DCOL 系列 4 次失败，v4 重复了 v1 完全相同的错误（margin_lr=1e-3 导致 embedding collapse）。Worker 写 spec 时未查阅同系列历史教训。）
- **C002**: 提交 DCOL 系列新实验前必须先 read_registry 检查同系列所有历史实验的失败原因和参数约束（原因：DCOL v4 重复了 v1 完全相同的错误（margin_lr=1e-3 导致 embedding collapse），系列已连续 4 次失败。Worker 未查阅历史教训直接提交。）


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
你是论文写作 Worker。任务：扩充 bibliography + 术语一致性审查 + orphan bib 清理。

## 目标文件
- `/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib` — bibliography
- 所有 .tex 文件在 `/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/` 目录下

## 任务 1: Bibliography 扩充至 25+ refs (R2-N2)

当前 bib 可能不足 25 条。必须覆盖以下领域（Dream D002 硬约束）：

**必须包含的引用**：
- Watermarking: Kirchenbauer et al. (ICML 2023) "A Watermark for Large Language Models"
- Model collapse theory: Alemohammad et al. (ICLR 2024) "Self-Consuming Generative Models Go MAD"; Dohmatob et al. (2024) "A tale of tails"; Gerstgrasser et al. (2024) accumulation; Shumailov et al. (Nature 2024) "AI models collapse"
- Data curation: DSIR (Xie et al. 2023), QuRating
- Multi-source attribution: Uchendu et al. (2020)
- Binary detectors: Binoculars (Hans et al. ICML 2024), Fast-DetectGPT (Bao et al. 2024), DivEye
- Decoding strategy effects: Garces Arias et al. (COLING 2025), Holtzman et al. (ICLR 2020) nucleus sampling
- Detection limits: Sadasivan et al. (2023) paraphrase attack
- Ordinal methods: CORAL (Cao et al. 2020), CLOC
- Model collapse + detection: Drayson et al. (EMNLP 2025)
- EditLens: recent work on editing extent estimation
- Bakshi et al. (2026): non-monotonic dynamics
- Marchi et al. (2024): temperature convergence theory
- Pudasaini et al. (2026): feature fragility under distribution shift
- Falahati et al. (2026): curated pipelines
- Sugiyama et al. (2007): covariate shift theory
- LoRA: Hu et al. (2022)

**方法**: 用 WebSearch 搜索每篇论文获取准确的 bib 信息（作者、标题、venue、年份、页码）。不要凭记忆编造 bib 条目——必须搜索确认。对于 2025-2026 年的论文，搜索时加 "arxiv" 或 "proceedings" 关键词。

生成标准 BibTeX 格式，key 命名规则：`firstauthor_year_shortname`（如 `kirchenbauer2023watermark`）。

## 任务 2: 术语一致性审查 (R2-W2)

扫描所有 .tex 文件，统一以下术语：
- "recursive generation depth" vs "generation depth" vs "recursive depth" vs "iteration depth" — 统一为 **"recursive generation depth"**（首次出现全称，后续可缩写为 "generation depth"）
- "depth degradation" vs "quality degradation" — 统一
- "statistical features" vs "hand-crafted features" vs "perplexity features" — 统一措辞
- "model collapse" vs "recursive collapse" — 按文献标准用法
- 确认 EDD 缩写在首次出现时定义

## 任务 3: Orphan bib 清理 (R2-W6)

1. 扫描 references.bib 中所有 bib key
2. 在所有 .tex 文件中搜索 \cite{key} 引用
3. 列出 bib 中存在但正文未引用的 orphan entries
4. 暂不删除 orphan（可能后续 section 会引用），只在文件末尾用注释标记

## 验证
完成后统计 bib 条目总数，确认 ≥ 25。列出新增的引用清单。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "56393c3b-ed02-4fb7-ae22-d9e02f92994c",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-15T15:51:11.412Z_

```json
{
  "parentUuid": "56393c3b-ed02-4fb7-ae22-d9e02f92994c",
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
  "uuid": "1cc200bf-9217-4aad-8dfc-df637c4ec2e0",
  "timestamp": "2026-05-15T15:51:11.412Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-15T15:51:11.412Z_

```json
{
  "parentUuid": "1cc200bf-9217-4aad-8dfc-df637c4ec2e0",
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
  "uuid": "d58c48df-ee4f-40dc-9e99-0b9cdd2198db",
  "timestamp": "2026-05-15T15:51:11.412Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-15T15:51:11.412Z_

```json
{
  "parentUuid": "d58c48df-ee4f-40dc-9e99-0b9cdd2198db",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "d9bdbbb1-2ce5-4b36-a8ba-7cf733d405d3",
  "timestamp": "2026-05-15T15:51:11.412Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
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
  "aiTitle": "Expand bibliography and verify paper terminology consistency",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Assistant

_source line 8 · 2026-05-15T15:51:14.651Z_

I'll start by reading the current state of the bib file and all .tex files to understand what exists.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d9bdbbb1-2ce5-4b36-a8ba-7cf733d405d3",
  "isSidechain": false,
  "requestId": "req_011Cb4cyqQiFi8wUjwjW3s2R",
  "type": "assistant",
  "uuid": "ed24e491-64ff-405e-80ff-18f3d0355b2e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VtcoHZp83eqiNd8chf8cW7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12269,
      "cache_read_input_tokens": 11841,
      "output_tokens": 200,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12269,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 200,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12269
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-15T15:51:15.218Z_

<details open><summary>🔧 Tool call — Read · `toolu_019pYFLdGB9rnfGJL7sSqq28`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ed24e491-64ff-405e-80ff-18f3d0355b2e",
  "isSidechain": false,
  "requestId": "req_011Cb4cyqQiFi8wUjwjW3s2R",
  "type": "assistant",
  "uuid": "4ef635d8-e3e0-4110-8d63-dc42b07c2784",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VtcoHZp83eqiNd8chf8cW7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12269,
      "cache_read_input_tokens": 11841,
      "output_tokens": 200,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12269,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 200,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12269
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-15T15:51:15.232Z_

<details><summary>↩ Tool result · `toolu_019pYFLdGB9rnfGJL7sSqq28`</summary>

```text
1	@article{shumailov2024_nature,
2	  author    = {Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},
3	  title     = {{AI models collapse when trained on recursively generated data}},
4	  journal   = {Nature},
5	  year      = {2024},
6	  doi       = {10.1038/s41586-024-07566-y},
7	}
8	
9	@inproceedings{marchi2024_heat_death,
10	  author    = {Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo},
11	  title     = {{Heat Death of Generative Models in Closed-Loop Learning}},
12	  booktitle = {Proceedings of ICASSP},
13	  year      = {2024},
14	  note      = {arXiv:2404.02325},
15	  url       = {https://arxiv.org/abs/2404.02325},
16	}
17	
18	@inproceedings{dohmatob2024_tale_of_tails,
19	  author    = {Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, Julia},
20	  title     = {{A Tale of Tails: Model Collapse as a Change of Scaling Laws}},
21	  booktitle = {Proceedings of ICML},
22	  year      = {2024},
23	  note      = {arXiv:2402.07043},
24	  url       = {https://arxiv.org/abs/2402.07043},
25	}
26	
27	@inproceedings{dohmatob2024_strong_collapse,
28	  author    = {Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia},
29	  title     = {{Strong Model Collapse}},
30	  booktitle = {Proceedings of ICLR},
31	  year      = {2024},
32	  note      = {arXiv:2410.04840},
33	  url       = {https://arxiv.org/abs/2410.04840},
34	}
35	
36	@inproceedings{dohmatob2024_demystified,
37	  author    = {Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia},
38	  title     = {{Model Collapse Demystified: The Case of Regression}},
39	  booktitle = {Proceedings of NeurIPS},
40	  year      = {2024},
41	  note      = {arXiv:2402.07712},
42	  url       = {https://arxiv.org/abs/2402.07712},
43	}
44	
45	@inproceedings{mohamed2025_broken_telephone,
46	  author    = {Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan},
47	  title     = {{LLM as a Broken Telephone: Iterative Generation Distorts Information}},
48	  booktitle = {Proceedings of ACL},
49	  year      = {2025},
50	  note      = {arXiv:2502.20258},
51	  url       = {https://arxiv.org/abs/2502.20258},
52	}
53	
54	@inproceedings{cloc2025,
55	  author    = {Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting},
56	  title     = {{CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss}},
57	  booktitle = {Proceedings of CVPR},
58	  year      = {2025},
59	  note      = {arXiv:2504.17813},
60	  url       = {https://arxiv.org/abs/2504.17813},
61	}
62	
63	@inproceedings{alemohammad2024_mad,
64	  author    = {Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and others},
65	  title     = {{Self-Consuming Generative Models Go MAD}},
66	  booktitle = {Proceedings of ICLR},
67	  year      = {2024},
68	  note      = {arXiv:2307.01850},
69	  url       = {https://arxiv.org/abs/2307.01850},
70	}
71	
72	@misc{gerstgrasser2024_accumulate,
73	  author    = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and others},
74	  title     = {{Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data}},
75	  year      = {2024},
76	  howpublished = {arXiv:2404.01413},
77	  url       = {https://arxiv.org/abs/2404.01413},
78	}
79	
80	@inproceedings{drayson2025_detection_prevents_collapse,
81	  author    = {Drayson, George and Yilmaz, Emine and Lampos, Vasileios},
82	  title     = {{Machine-generated text detection prevents language model collapse}},
83	  booktitle = {Findings of EMNLP},
84	  year      = {2025},
85	  note      = {arXiv:2502.15654},
86	  url       = {https://arxiv.org/abs/2502.15654},
87	}
88	
89	@misc{bakshi2026_collapse_improvement,
90	  author    = {Bakshi, Soham and Chakraborty, Sunrit},
91	  title     = {{From Collapse to Improvement: Statistical Perspectives on Iterative Training}},
92	  year      = {2026},
93	  howpublished = {arXiv:2602.10531},
94	  url       = {https://arxiv.org/abs/2602.10531},
95	}
96	
97	@misc{wang2026_contamination,
98	  author    = {Wang, Kevin and Niu, Hongqian and Li, Didong},
99	  title     = {{Can Generative AI Survive Data Contamination? Theoretical Guarantees}},
100	  year      = {2026},
101	  howpublished = {arXiv:2602.16065},
102	  url       = {https://arxiv.org/abs/2602.16065},
103	}
104	
105	@misc{falahati2026_curated,
106	  author    = {Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz},
107	  title     = {{Curated Synthetic Data Doesn't Have to Collapse}},
108	  year      = {2026},
109	  howpublished = {arXiv:2605.07724},
110	  url       = {https://arxiv.org/abs/2605.07724},
111	}
112	
113	@misc{knowledge_collapse2025,
114	  author    = {Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven, Philip},
115	  title     = {{Knowledge Collapse in LLMs: Fluency Survives but Facts Fail}},
116	  year      = {2025},
117	  howpublished = {arXiv:2509.04796},
118	  url       = {https://arxiv.org/abs/2509.04796},
119	}
120	
121	@inproceedings{synthetic_eggs2026,
122	  author    = {Schaffelder, Max and Gatt, Albert},
123	  title     = {{Synthetic Eggs in Many Baskets: Impact of Synthetic Data Diversity on LLM Fine-Tuning}},
124	  booktitle = {Findings of ACL},
125	  year      = {2026},
126	  note      = {arXiv:2511.01490},
127	  url       = {https://arxiv.org/abs/2511.01490},
128	}
129	
130	
131	@misc{sigma2026_spectral,
132	  author    = {Gu, Yi and Pang, Lingyou and Ye, Xiangkun and others},
133	  title     = {{SIGMA: Scalable Spectral Insights for LLM Model Collapse}},
134	  year      = {2026},
135	  howpublished = {arXiv:2601.03385},
136	  url       = {https://arxiv.org/abs/2601.03385},
137	}
138	
139	@inproceedings{holtzman2020_nucleus,
140	  author    = {Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin},
141	  title     = {{The Curious Case of Neural Text Degeneration}},
142	  booktitle = {Proceedings of ICLR},
143	  year      = {2020},
144	  note      = {arXiv:1904.09751},
145	  url       = {https://arxiv.org/abs/1904.09751},
146	}
147	
148	@inproceedings{finlayson2024_closing,
149	  author    = {Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabha and Sabharwal, Ashish},
150	  title     = {{Closing the Curious Case of Neural Text Degeneration}},
151	  booktitle = {Proceedings of ICLR},
152	  year      = {2024},
153	  note      = {arXiv:2310.01693},
154	  url       = {https://arxiv.org/abs/2310.01693},
155	}
156	
157	@inproceedings{garces_arias2025_decoding_decoded,
158	  author    = {{Garces Arias}, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher, Matthias},
159	  title     = {{Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation}},
160	  booktitle = {Proceedings of COLING},
161	  year      = {2025},
162	}
163	
164	@article{wiher2022_decoding,
165	  author    = {Wiher, Gian and Meister, Clara and Cotterell, Ryan},
166	  title     = {{On Decoding Strategies for Neural Text Generators}},
167	  journal   = {Transactions of the Association for Computational Linguistics},
168	  year      = {2022},
169	}
170	
171	@inproceedings{basu2021_mirostat,
172	  author    = {Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shirish and Varshney, Lav R.},
173	  title     = {{Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity}},
174	  booktitle = {Proceedings of ICLR},
175	  year      = {2021},
176	}
177	
178	@inproceedings{mitchell2023_detectgpt,
179	  author    = {Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},
180	  title     = {{DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature}},
181	  booktitle = {Proceedings of ICML},
182	  year      = {2023},
183	  note      = {arXiv:2301.11305},
184	  url       = {https://arxiv.org/abs/2301.11305},
185	}
186	
187	@misc{sadasivan2023_paraphrase,
188	  author    = {Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, Wenxiao and Feizi, Soheil},
189	  title     = {{Can AI-Generated Text be Reliably Detected?}},
190	  year      = {2023},
191	  howpublished = {arXiv:2303.11156},
192	  url       = {https://arxiv.org/abs/2303.11156},
193	}
194	
195	@inproceedings{binoculars2024,
196	  author    = {Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and others},
197	  title     = {{Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text}},
198	  booktitle = {Proceedings of ICML},
199	  year      = {2024},
200	  note      = {arXiv:2401.12070},
201	  url       = {https://arxiv.org/abs/2401.12070},
202	}
203	
204	@inproceedings{fast_detectgpt2024,
205	  author    = {Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yue},
206	  title     = {{Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature}},
207	  booktitle = {Proceedings of ICLR},
208	  year      = {2024},
209	  note      = {arXiv:2310.05130},
210	  url       = {https://arxiv.org/abs/2310.05130},
211	}
212	
213	@inproceedings{diveye2026,
214	  author    = {Basani, Advik Raj and Chen, Pin-Yu},
215	  title     = {{DivEye: Diversity Boosts AI-Generated Text Detection}},
216	  booktitle = {Proceedings of ICLR},
217	  year      = {2026},
218	  note      = {arXiv:2509.18880},
219	  url       = {https://arxiv.org/abs/2509.18880},
220	}
221	
222	@inproceedings{loki2025,
223	  author    = {Ye, Junyan and Zhou, Baichuan and Huang, Zilong and others},
224	  title     = {{LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models}},
225	  booktitle = {Proceedings of ICLR},
226	  year      = {2025},
227	  note      = {arXiv:2410.09732},
228	  url       = {https://arxiv.org/abs/2410.09732},
229	}
230	
231	@inproceedings{gehrmann2019_gltr,
232	  author    = {Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.},
233	  title     = {{GLTR: Statistical Detection and Visualization of Generated Text}},
234	  booktitle = {Proceedings of ACL},
235	  year      = {2019},
236	  note      = {arXiv:1906.04043},
237	  url       = {https://arxiv.org/abs/1906.04043},
238	}
239	
240	@misc{pudasaini2026_detection_fails,
241	  author    = {Pudasaini, Shushanta and Miralles-Pech{\'u}an, Luis and Lillis, David and Llorens Salvador, Marisa},
242	  title     = {{Why AI-Generated Text Detection Fails: Evidence from Explainable AI}},
243	  year      = {2026},
244	  howpublished = {arXiv:2603.23146},
245	  url       = {https://arxiv.org/abs/2603.23146},
246	}
247	
248	@inproceedings{editlens2026,
249	  author    = {Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit},
250	  title     = {{EditLens: Quantifying the Extent of AI Editing in Text}},
251	  booktitle = {Proceedings of ICLR},
252	  year      = {2026},
253	  note      = {arXiv:2510.03154},
254	  url       = {https://arxiv.org/abs/2510.03154},
255	}
256	
257	@inproceedings{uchendu2020_attribution,
258	  author    = {Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon},
259	  title     = {{Authorship Attribution for Neural Text Generation}},
260	  booktitle = {Proceedings of EMNLP},
261	  year      = {2020},
262	}
263	
264	@misc{pu2026_generator_barrier,
265	  author    = {Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli},
266	  title     = {{Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection}},
267	  year      = {2026},
268	  howpublished = {arXiv:2604.13692},
269	  url       = {https://arxiv.org/abs/2604.13692},
270	}
271	
272	@article{coral2020,
273	  author    = {Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian},
274	  title     = {{Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation}},
275	  journal   = {Pattern Recognition Letters},
276	  year      = {2020},
277	  note      = {arXiv:1901.07884},
278	  url       = {https://arxiv.org/abs/1901.07884},
279	}
280	
281	
282	@inproceedings{kirchenbauer2023_watermark,
283	  author    = {Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Miers, Ian and Goldstein, Tom},
284	  title     = {{A Watermark for Large Language Models}},
285	  booktitle = {Proceedings of ICML},
286	  year      = {2023},
287	  note      = {arXiv:2301.10226},
288	  url       = {https://arxiv.org/abs/2301.10226},
289	}
290	
291	@inproceedings{dsir2023,
292	  author    = {Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},
293	  title     = {{Data Selection for Language Models via Importance Resampling}},
294	  booktitle = {Proceedings of NeurIPS},
295	  year      = {2023},
296	  note      = {arXiv:2302.03169},
297	  url       = {https://arxiv.org/abs/2302.03169},
298	}
299	
300	@inproceedings{qurating2024,
301	  author    = {Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},
302	  title     = {{QuRating: Selecting High-Quality Data for Training Language Models}},
303	  booktitle = {Proceedings of ICML},
304	  year      = {2024},
305	  note      = {arXiv:2402.09739},
306	  url       = {https://arxiv.org/abs/2402.09739},
307	}
308	
309	@inproceedings{hu2022lora,
310	  author    = {Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},
311	  title     = {{LoRA: Low-Rank Adaptation of Large Language Models}},
312	  booktitle = {Proceedings of ICLR},
313	  year      = {2022},
314	  note      = {arXiv:2106.09685},
315	  url       = {https://arxiv.org/abs/2106.09685},
316	}
317	
318	@article{sugiyama2007_importance_weighting,
319	  author    = {Sugiyama, Masashi and Krauledat, Matthias and M{\"u}ller, Klaus-Robert},
320	  title     = {{Covariate Shift Adaptation by Importance Weighted Cross Validation}},
321	  journal   = {Journal of Machine Learning Research},
322	  year      = {2007},
323	}
324	
325	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4ef635d8-e3e0-4110-8d63-dc42b07c2784",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "92335bb2-e789-4b05-845c-689de9e0a18c",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib",
      "content": "@article{shumailov2024_nature,\n  author    = {Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},\n  title     = {{AI models collapse when trained on recursively generated data}},\n  journal   = {Nature},\n  year      = {2024},\n  doi       = {10.1038/s41586-024-07566-y},\n}\n\n@inproceedings{marchi2024_heat_death,\n  author    = {Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo},\n  title     = {{Heat Death of Generative Models in Closed-Loop Learning}},\n  booktitle = {Proceedings of ICASSP},\n  year      = {2024},\n  note      = {arXiv:2404.02325},\n  url       = {https://arxiv.org/abs/2404.02325},\n}\n\n@inproceedings{dohmatob2024_tale_of_tails,\n  author    = {Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, Julia},\n  title     = {{A Tale of Tails: Model Collapse as a Change of Scaling Laws}},\n  booktitle = {Proceedings of ICML},\n  year      = {2024},\n  note      = {arXiv:2402.07043},\n  url       = {https://arxiv.org/abs/2402.07043},\n}\n\n@inproceedings{dohmatob2024_strong_collapse,\n  author    = {Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia},\n  title     = {{Strong Model Collapse}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2410.04840},\n  url       = {https://arxiv.org/abs/2410.04840},\n}\n\n@inproceedings{dohmatob2024_demystified,\n  author    = {Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia},\n  title     = {{Model Collapse Demystified: The Case of Regression}},\n  booktitle = {Proceedings of NeurIPS},\n  year      = {2024},\n  note      = {arXiv:2402.07712},\n  url       = {https://arxiv.org/abs/2402.07712},\n}\n\n@inproceedings{mohamed2025_broken_telephone,\n  author    = {Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan},\n  title     = {{LLM as a Broken Telephone: Iterative Generation Distorts Information}},\n  booktitle = {Proceedings of ACL},\n  year      = {2025},\n  note      = {arXiv:2502.20258},\n  url       = {https://arxiv.org/abs/2502.20258},\n}\n\n@inproceedings{cloc2025,\n  author    = {Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting},\n  title     = {{CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss}},\n  booktitle = {Proceedings of CVPR},\n  year      = {2025},\n  note      = {arXiv:2504.17813},\n  url       = {https://arxiv.org/abs/2504.17813},\n}\n\n@inproceedings{alemohammad2024_mad,\n  author    = {Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and others},\n  title     = {{Self-Consuming Generative Models Go MAD}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2307.01850},\n  url       = {https://arxiv.org/abs/2307.01850},\n}\n\n@misc{gerstgrasser2024_accumulate,\n  author    = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and others},\n  title     = {{Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data}},\n  year      = {2024},\n  howpublished = {arXiv:2404.01413},\n  url       = {https://arxiv.org/abs/2404.01413},\n}\n\n@inproceedings{drayson2025_detection_prevents_collapse,\n  author    = {Drayson, George and Yilmaz, Emine and Lampos, Vasileios},\n  title     = {{Machine-generated text detection prevents language model collapse}},\n  booktitle = {Findings of EMNLP},\n  year      = {2025},\n  note      = {arXiv:2502.15654},\n  url       = {https://arxiv.org/abs/2502.15654},\n}\n\n@misc{bakshi2026_collapse_improvement,\n  author    = {Bakshi, Soham and Chakraborty, Sunrit},\n  title     = {{From Collapse to Improvement: Statistical Perspectives on Iterative Training}},\n  year      = {2026},\n  howpublished = {arXiv:2602.10531},\n  url       = {https://arxiv.org/abs/2602.10531},\n}\n\n@misc{wang2026_contamination,\n  author    = {Wang, Kevin and Niu, Hongqian and Li, Didong},\n  title     = {{Can Generative AI Survive Data Contamination? Theoretical Guarantees}},\n  year      = {2026},\n  howpublished = {arXiv:2602.16065},\n  url       = {https://arxiv.org/abs/2602.16065},\n}\n\n@misc{falahati2026_curated,\n  author    = {Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz},\n  title     = {{Curated Synthetic Data Doesn't Have to Collapse}},\n  year      = {2026},\n  howpublished = {arXiv:2605.07724},\n  url       = {https://arxiv.org/abs/2605.07724},\n}\n\n@misc{knowledge_collapse2025,\n  author    = {Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven, Philip},\n  title     = {{Knowledge Collapse in LLMs: Fluency Survives but Facts Fail}},\n  year      = {2025},\n  howpublished = {arXiv:2509.04796},\n  url       = {https://arxiv.org/abs/2509.04796},\n}\n\n@inproceedings{synthetic_eggs2026,\n  author    = {Schaffelder, Max and Gatt, Albert},\n  title     = {{Synthetic Eggs in Many Baskets: Impact of Synthetic Data Diversity on LLM Fine-Tuning}},\n  booktitle = {Findings of ACL},\n  year      = {2026},\n  note      = {arXiv:2511.01490},\n  url       = {https://arxiv.org/abs/2511.01490},\n}\n\n\n@misc{sigma2026_spectral,\n  author    = {Gu, Yi and Pang, Lingyou and Ye, Xiangkun and others},\n  title     = {{SIGMA: Scalable Spectral Insights for LLM Model Collapse}},\n  year      = {2026},\n  howpublished = {arXiv:2601.03385},\n  url       = {https://arxiv.org/abs/2601.03385},\n}\n\n@inproceedings{holtzman2020_nucleus,\n  author    = {Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin},\n  title     = {{The Curious Case of Neural Text Degeneration}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2020},\n  note      = {arXiv:1904.09751},\n  url       = {https://arxiv.org/abs/1904.09751},\n}\n\n@inproceedings{finlayson2024_closing,\n  author    = {Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabha and Sabharwal, Ashish},\n  title     = {{Closing the Curious Case of Neural Text Degeneration}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2310.01693},\n  url       = {https://arxiv.org/abs/2310.01693},\n}\n\n@inproceedings{garces_arias2025_decoding_decoded,\n  author    = {{Garces Arias}, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher, Matthias},\n  title     = {{Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation}},\n  booktitle = {Proceedings of COLING},\n  year      = {2025},\n}\n\n@article{wiher2022_decoding,\n  author    = {Wiher, Gian and Meister, Clara and Cotterell, Ryan},\n  title     = {{On Decoding Strategies for Neural Text Generators}},\n  journal   = {Transactions of the Association for Computational Linguistics},\n  year      = {2022},\n}\n\n@inproceedings{basu2021_mirostat,\n  author    = {Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shirish and Varshney, Lav R.},\n  title     = {{Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2021},\n}\n\n@inproceedings{mitchell2023_detectgpt,\n  author    = {Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},\n  title     = {{DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature}},\n  booktitle = {Proceedings of ICML},\n  year      = {2023},\n  note      = {arXiv:2301.11305},\n  url       = {https://arxiv.org/abs/2301.11305},\n}\n\n@misc{sadasivan2023_paraphrase,\n  author    = {Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, Wenxiao and Feizi, Soheil},\n  title     = {{Can AI-Generated Text be Reliably Detected?}},\n  year      = {2023},\n  howpublished = {arXiv:2303.11156},\n  url       = {https://arxiv.org/abs/2303.11156},\n}\n\n@inproceedings{binoculars2024,\n  author    = {Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and others},\n  title     = {{Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text}},\n  booktitle = {Proceedings of ICML},\n  year      = {2024},\n  note      = {arXiv:2401.12070},\n  url       = {https://arxiv.org/abs/2401.12070},\n}\n\n@inproceedings{fast_detectgpt2024,\n  author    = {Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yue},\n  title     = {{Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2024},\n  note      = {arXiv:2310.05130},\n  url       = {https://arxiv.org/abs/2310.05130},\n}\n\n@inproceedings{diveye2026,\n  author    = {Basani, Advik Raj and Chen, Pin-Yu},\n  title     = {{DivEye: Diversity Boosts AI-Generated Text Detection}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2026},\n  note      = {arXiv:2509.18880},\n  url       = {https://arxiv.org/abs/2509.18880},\n}\n\n@inproceedings{loki2025,\n  author    = {Ye, Junyan and Zhou, Baichuan and Huang, Zilong and others},\n  title     = {{LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2025},\n  note      = {arXiv:2410.09732},\n  url       = {https://arxiv.org/abs/2410.09732},\n}\n\n@inproceedings{gehrmann2019_gltr,\n  author    = {Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.},\n  title     = {{GLTR: Statistical Detection and Visualization of Generated Text}},\n  booktitle = {Proceedings of ACL},\n  year      = {2019},\n  note      = {arXiv:1906.04043},\n  url       = {https://arxiv.org/abs/1906.04043},\n}\n\n@misc{pudasaini2026_detection_fails,\n  author    = {Pudasaini, Shushanta and Miralles-Pech{\\'u}an, Luis and Lillis, David and Llorens Salvador, Marisa},\n  title     = {{Why AI-Generated Text Detection Fails: Evidence from Explainable AI}},\n  year      = {2026},\n  howpublished = {arXiv:2603.23146},\n  url       = {https://arxiv.org/abs/2603.23146},\n}\n\n@inproceedings{editlens2026,\n  author    = {Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit},\n  title     = {{EditLens: Quantifying the Extent of AI Editing in Text}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2026},\n  note      = {arXiv:2510.03154},\n  url       = {https://arxiv.org/abs/2510.03154},\n}\n\n@inproceedings{uchendu2020_attribution,\n  author    = {Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon},\n  title     = {{Authorship Attribution for Neural Text Generation}},\n  booktitle = {Proceedings of EMNLP},\n  year      = {2020},\n}\n\n@misc{pu2026_generator_barrier,\n  author    = {Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli},\n  title     = {{Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection}},\n  year      = {2026},\n  howpublished = {arXiv:2604.13692},\n  url       = {https://arxiv.org/abs/2604.13692},\n}\n\n@article{coral2020,\n  author    = {Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian},\n  title     = {{Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation}},\n  journal   = {Pattern Recognition Letters},\n  year      = {2020},\n  note      = {arXiv:1901.07884},\n  url       = {https://arxiv.org/abs/1901.07884},\n}\n\n\n@inproceedings{kirchenbauer2023_watermark,\n  author    = {Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Miers, Ian and Goldstein, Tom},\n  title     = {{A Watermark for Large Language Models}},\n  booktitle = {Proceedings of ICML},\n  year      = {2023},\n  note      = {arXiv:2301.10226},\n  url       = {https://arxiv.org/abs/2301.10226},\n}\n\n@inproceedings{dsir2023,\n  author    = {Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},\n  title     = {{Data Selection for Language Models via Importance Resampling}},\n  booktitle = {Proceedings of NeurIPS},\n  year      = {2023},\n  note      = {arXiv:2302.03169},\n  url       = {https://arxiv.org/abs/2302.03169},\n}\n\n@inproceedings{qurating2024,\n  author    = {Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},\n  title     = {{QuRating: Selecting High-Quality Data for Training Language Models}},\n  booktitle = {Proceedings of ICML},\n  year      = {2024},\n  note      = {arXiv:2402.09739},\n  url       = {https://arxiv.org/abs/2402.09739},\n}\n\n@inproceedings{hu2022lora,\n  author    = {Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},\n  title     = {{LoRA: Low-Rank Adaptation of Large Language Models}},\n  booktitle = {Proceedings of ICLR},\n  year      = {2022},\n  note      = {arXiv:2106.09685},\n  url       = {https://arxiv.org/abs/2106.09685},\n}\n\n@article{sugiyama2007_importance_weighting,\n  author    = {Sugiyama, Masashi and Krauledat, Matthias and M{\\\"u}ller, Klaus-Robert},\n  title     = {{Covariate Shift Adaptation by Importance Weighted Cross Validation}},\n  journal   = {Journal of Machine Learning Research},\n  year      = {2007},\n}\n\n",
      "numLines": 325,
      "startLine": 1,
      "totalLines": 325
    }
  },
  "sourceToolAssistantUUID": "4ef635d8-e3e0-4110-8d63-dc42b07c2784",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-15T15:51:15.648Z_

<details><summary>↩ Tool result · `toolu_017VeoBZefXh7UuHBJYmntQ9`</summary>

```text
docs/paper/main.tex
docs/paper/abstract.tex
docs/paper/section_appendix.tex
docs/paper/conclusion.tex
docs/paper/related_work.tex
docs/paper/discussion.tex
docs/paper/generalization.tex
docs/paper/method.tex
docs/paper/atlas.tex
docs/paper/introduction.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0d83311d-1fe3-4454-bd14-be913bab3e80",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "3c64bee2-1095-4687-bbb6-31f9a63816e7",
  "toolUseResult": {
    "filenames": [
      "docs/paper/main.tex",
      "docs/paper/abstract.tex",
      "docs/paper/section_appendix.tex",
      "docs/paper/conclusion.tex",
      "docs/paper/related_work.tex",
      "docs/paper/discussion.tex",
      "docs/paper/generalization.tex",
      "docs/paper/method.tex",
      "docs/paper/atlas.tex",
      "docs/paper/introduction.tex"
    ],
    "durationMs": 14,
    "numFiles": 10,
    "truncated": false
  },
  "sourceToolAssistantUUID": "0d83311d-1fe3-4454-bd14-be913bab3e80",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-15T15:51:15.630Z_

<details open><summary>🔧 Tool call — Glob · `toolu_017VeoBZefXh7UuHBJYmntQ9`</summary>

```json
{
  "pattern": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "92335bb2-e789-4b05-845c-689de9e0a18c",
  "isSidechain": false,
  "requestId": "req_011Cb4cyqQiFi8wUjwjW3s2R",
  "type": "assistant",
  "uuid": "0d83311d-1fe3-4454-bd14-be913bab3e80",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VtcoHZp83eqiNd8chf8cW7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12269,
      "cache_read_input_tokens": 11841,
      "output_tokens": 200,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12269,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 200,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12269
          },
          "type": "message"
        }
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
  "leafUuid": "3c64bee2-1095-4687-bbb6-31f9a63816e7",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Runtime record

_source line 14_

```json
{
  "type": "ai-title",
  "aiTitle": "Expand bibliography and verify paper terminology consistency",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Assistant

_source line 15 · 2026-05-15T15:51:34.187Z_

<details><summary>Logged reasoning block</summary>

```text
Current bib has 35 entries. Let me count them:

1. shumailov2024_nature
2. marchi2024_heat_death
3. dohmatob2024_tale_of_tails
4. dohmatob2024_strong_collapse
5. dohmatob2024_demystified
6. mohamed2025_broken_telephone
7. cloc2025
8. alemohammad2024_mad
9. gerstgrasser2024_accumulate
10. drayson2025_detection_prevents_collapse
11. bakshi2026_collapse_improvement


12. wang2026_contamination
13. falahati2026_curated
14. knowledge_collapse2025
15. synthetic_eggs2026
16. sigma2026_spectral
17. holtzman2020_nucleus
18. finlayson2024_closing
19. garces_arias2025_decoding_decoded
20. wiher2022_decoding
21. basu2021_mirostat
22. mitchell2023_detectgpt
23. sadasivan2023_paraphrase
24. binoculars2024
25. fast_detectgpt2024
26. diveye2026
27. loki2025
28. gehrmann2019_gltr
29. pudasaini

That's 29 so far, so I need 6 more entries to reach 35.

I'm continuing through the reference list and now I'm checking which of the key papers are already included. I can see Kirchenbauer et al.'s watermarking work is there, along with Alemohammad's MAD paper and the other critical references I need. Let me verify the remaining required citations are accounted for. I'm continuing through the detection methods, adding Sadasivan et al.'s paraphrase approach, CORAL, CLOC, and several recent papers on detection effectiveness and collapse prevention, along with foundational work on importance weighting and LoRA techniques.

All 38 references are accounted for, so now I need to verify the count meets the minimum, audit terminology consistency across the tex files, and clean up any orphaned citations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c64bee2-1095-4687-bbb6-31f9a63816e7",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "63aa6cba-00bb-41d0-9312-72de64ead8f3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 16 · 2026-05-15T15:51:34.190Z_

38 bib entries already present, all required references accounted for. Now reading all .tex files for terminology audit and citation scanning.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63aa6cba-00bb-41d0-9312-72de64ead8f3",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "b13eca47-2814-46c7-a40e-44525289f6a2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 17 · 2026-05-15T15:51:35.657Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RHsvXsbnD8iXCr9m8UcEdj`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b13eca47-2814-46c7-a40e-44525289f6a2",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "95a1852d-7c04-44d4-9321-9b952ad95290",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 18 · 2026-05-15T15:51:40.513Z_

<details><summary>↩ Tool result · `toolu_01CVzmM2uk8ioYHKE2kuHLUc`</summary>

```text
1	\section{Additional Results}
2	\label{app:additional}
3	
4	\subsection{Top-$k$ Feature Trajectories}
5	\label{app:topk_trajectories}
6	
7	Figure~\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\tau{=}0.9$) sampling.
8	Top-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \S\ref{sec:atlas:trajectories}.
9	Concretely, the d0$\to$d1 drop in \textsc{p90\_ppl} under top-$k$ is 78\% (vs.\ 87\% for nucleus), and the d2$\to$d3 reduction is 31\% (vs.\ 39\% for nucleus).
10	Despite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.
11	
12	\subsection{Permutation Importance}
13	\label{app:permutation}
14	
15	To verify that the Gini-based importance rankings in \S\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.
16	Results are highly consistent: \textsc{p90\_ppl} ranks in the top 2 in 9/9 cells under both measures, and \textsc{var\_surprisal} in 8/9 (vs.\ 7/9 for Gini, with the additional cell being OLMo top-$k$).
17	The mean Spearman rank correlation between Gini and permutation importance vectors across all 9 cells is $\rho{=}0.94$, confirming that the reported feature universality is robust to the choice of importance measure.
18	
19	\subsection{DCOL Iteration Details}
20	\label{app:dcol_iterations}
21	
22	Table~\ref{tab:dcol_iterations} summarizes all six DCOL iterations.
23	DeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.
24	
25	\begin{table}[h]
26	\centering
27	\small
28	\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\%.}
29	\label{tab:dcol_iterations}
30	\begin{tabular}{llll}
31	\toprule
32	Ver. & Backbone & Config & Outcome \\
33	\midrule
34	v1 & DeBERTa-large & Full FT, margin\_lr$\,{=}\,10^{-3}$ & Embed.\ collapse (acc 31.5\%) \\
35	v2 & DeBERTa-large & Full FT, margin\_lr$\,{=}\,10^{-4}$ & OOM (GPU contention) \\
36	v3 & DeBERTa-large & Full FT, margin\_lr$\,{=}\,10^{-4}$ & Forgetting $+$ OOM \\
37	v4 & DeBERTa-large & LoRA $r{=}16$, m\_lr$\,{=}\,10^{-3}$ & Embed.\ collapse (v1 repeat) \\
38	v5 & DeBERTa-large & LoRA $r{=}16$, m\_lr$\,{=}\,10^{-4}$ & NaN gradient explosion \\
39	v6 & RoBERTa-large & Full FT, grad clip 1.0 & Stable; acc 64.5\% ($-$13.7pp) \\
40	\bottomrule
41	\end{tabular}
42	\end{table}
43	
44	\subsection{Feature Overlap Analysis}
45	\label{app:feature_overlap}
46	
47	We probe whether end-to-end PLM representations capture the same depth signals as our statistical features.
48	DeBERTa attention importance and RF permutation importance exhibit a significant negative correlation (Spearman $\rho{=}{-}0.484$, $p{=}0.036$; top-5 Jaccard overlap$\,{=}\,0$).
49	PLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics---\textsc{var\_surprisal} and \textsc{p90\_ppl} yield negative $R^2$ under linear probing.
50	This confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\S\ref{sec:gen:dcol}) stems from complementary---not redundant---representations: PLMs capture lexical patterns while the statistical features capture distributional tail properties that constitute the dominant depth markers.
51	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6f68218b-3d8b-44e4-b6fc-acbfab80aee9",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "efe18a27-23a5-4652-b0c5-c5d64b66e7d2",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
      "content": "\\section{Additional Results}\n\\label{app:additional}\n\n\\subsection{Top-$k$ Feature Trajectories}\n\\label{app:topk_trajectories}\n\nFigure~\\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\\tau{=}0.9$) sampling.\nTop-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \\S\\ref{sec:atlas:trajectories}.\nConcretely, the d0$\\to$d1 drop in \\textsc{p90\\_ppl} under top-$k$ is 78\\% (vs.\\ 87\\% for nucleus), and the d2$\\to$d3 reduction is 31\\% (vs.\\ 39\\% for nucleus).\nDespite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.\n\n\\subsection{Permutation Importance}\n\\label{app:permutation}\n\nTo verify that the Gini-based importance rankings in \\S\\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.\nResults are highly consistent: \\textsc{p90\\_ppl} ranks in the top 2 in 9/9 cells under both measures, and \\textsc{var\\_surprisal} in 8/9 (vs.\\ 7/9 for Gini, with the additional cell being OLMo top-$k$).\nThe mean Spearman rank correlation between Gini and permutation importance vectors across all 9 cells is $\\rho{=}0.94$, confirming that the reported feature universality is robust to the choice of importance measure.\n\n\\subsection{DCOL Iteration Details}\n\\label{app:dcol_iterations}\n\nTable~\\ref{tab:dcol_iterations} summarizes all six DCOL iterations.\nDeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\\%.}\n\\label{tab:dcol_iterations}\n\\begin{tabular}{llll}\n\\toprule\nVer. & Backbone & Config & Outcome \\\\\n\\midrule\nv1 & DeBERTa-large & Full FT, margin\\_lr$\\,{=}\\,10^{-3}$ & Embed.\\ collapse (acc 31.5\\%) \\\\\nv2 & DeBERTa-large & Full FT, margin\\_lr$\\,{=}\\,10^{-4}$ & OOM (GPU contention) \\\\\nv3 & DeBERTa-large & Full FT, margin\\_lr$\\,{=}\\,10^{-4}$ & Forgetting $+$ OOM \\\\\nv4 & DeBERTa-large & LoRA $r{=}16$, m\\_lr$\\,{=}\\,10^{-3}$ & Embed.\\ collapse (v1 repeat) \\\\\nv5 & DeBERTa-large & LoRA $r{=}16$, m\\_lr$\\,{=}\\,10^{-4}$ & NaN gradient explosion \\\\\nv6 & RoBERTa-large & Full FT, grad clip 1.0 & Stable; acc 64.5\\% ($-$13.7pp) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Feature Overlap Analysis}\n\\label{app:feature_overlap}\n\nWe probe whether end-to-end PLM representations capture the same depth signals as our statistical features.\nDeBERTa attention importance and RF permutation importance exhibit a significant negative correlation (Spearman $\\rho{=}{-}0.484$, $p{=}0.036$; top-5 Jaccard overlap$\\,{=}\\,0$).\nPLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics---\\textsc{var\\_surprisal} and \\textsc{p90\\_ppl} yield negative $R^2$ under linear probing.\nThis confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\\S\\ref{sec:gen:dcol}) stems from complementary---not redundant---representations: PLMs capture lexical patterns while the statistical features capture distributional tail properties that constitute the dominant depth markers.\n",
      "numLines": 51,
      "startLine": 1,
      "totalLines": 51
    }
  },
  "sourceToolAssistantUUID": "6f68218b-3d8b-44e4-b6fc-acbfab80aee9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-15T15:51:35.666Z_

<details><summary>↩ Tool result · `toolu_01RHsvXsbnD8iXCr9m8UcEdj`</summary>

```text
1	% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints
2	% Target: EMNLP 2026 (ARR May cycle)
3	\documentclass[11pt]{article}
4	\usepackage[review]{acl}
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage{graphicx}
8	\usepackage{booktabs}
9	\usepackage{amsmath}
10	\usepackage{amssymb}
11	\usepackage{multirow}
12	\usepackage{xcolor}
13	\usepackage{subcaption}
14	\usepackage[T1]{fontenc}
15	\usepackage[utf8]{inputenc}
16	\usepackage{microtype}
17	
18	\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\via Statistical Fingerprints}
19	
20	\author{Anonymous}
21	
22	\begin{document}
23	\maketitle
24	
25	\input{abstract}
26	
27	\input{introduction}
28	
29	\input{related_work}
30	
31	\input{method}
32	
33	\input{atlas}
34	
35	\input{generalization}
36	
37	\input{discussion}
38	
39	\input{conclusion}
40	
41	\bibliography{references}
42	
43	\appendix
44	\input{section_appendix}
45	
46	\end{document}
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "95a1852d-7c04-44d4-9321-9b952ad95290",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "89eb0599-7f68-4029-8a4e-22bb2a6e67d4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex",
      "content": "% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\n% Target: EMNLP 2026 (ARR May cycle)\n\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\n\\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\\\via Statistical Fingerprints}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{method}\n\n\\input{atlas}\n\n\\input{generalization}\n\n\\input{discussion}\n\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{section_appendix}\n\n\\end{document}\n",
      "numLines": 47,
      "startLine": 1,
      "totalLines": 47
    }
  },
  "sourceToolAssistantUUID": "95a1852d-7c04-44d4-9321-9b952ad95290",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 20 · 2026-05-15T15:51:36.069Z_

<details open><summary>🔧 Tool call — Read · `toolu_012UiXnsyUrXB1Ho6Z9rSbQT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "89eb0599-7f68-4029-8a4e-22bb2a6e67d4",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "f36064eb-0cb3-4296-8903-4ce63c81e229",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 21 · 2026-05-15T15:51:36.075Z_

<details><summary>↩ Tool result · `toolu_012UiXnsyUrXB1Ho6Z9rSbQT`</summary>

```text
1	\begin{abstract}
2	As large language models increasingly train on web text containing their own outputs, a recursive model$\to$data$\to$model loop arises---yet no method estimates how many such iterations a text has undergone.
3	We formalize \emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.
4	From each passage we extract 19 statistical features---perplexity percentiles, surprisal moments, and lexical diversity measures---computed against a fixed reference model (GPT-2 base, 124M).
5	A Random Forest classifier achieves 70--85\% four-class accuracy (chance = 25\%; a zero-shot LLM baseline reaches only 40\%), with 90th-percentile perplexity and surprisal variance emerging as universal depth markers (top-2 importance in 9/9 and 7/9 model--strategy cells, respectively; mean Spearman $\rho{=}0.868$).
6	Our \emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \emph{Effective Discriminable Depth} (EDD) metric, finding $\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.
7	Cross-model transfer reaches 66.4\% and cross-strategy transfer 59.1\%, though temperature sampling induces a d1/d2 AUC inversion that z-score normalization cannot resolve.
8	\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f36064eb-0cb3-4296-8903-4ce63c81e229",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "05d9a721-a772-44c8-81ad-432e08e0421e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises---yet no method estimates how many such iterations a text has undergone.\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.\nFrom each passage we extract 19 statistical features---perplexity percentiles, surprisal moments, and lexical diversity measures---computed against a fixed reference model (GPT-2 base, 124M).\nA Random Forest classifier achieves 70--85\\% four-class accuracy (chance = 25\\%; a zero-shot LLM baseline reaches only 40\\%), with 90th-percentile perplexity and surprisal variance emerging as universal depth markers (top-2 importance in 9/9 and 7/9 model--strategy cells, respectively; mean Spearman $\\rho{=}0.868$).\nOur \\emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.\nCross-model transfer reaches 66.4\\% and cross-strategy transfer 59.1\\%, though temperature sampling induces a d1/d2 AUC inversion that z-score normalization cannot resolve.\n\\end{abstract}",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "f36064eb-0cb3-4296-8903-4ce63c81e229",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-15T15:51:36.629Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XG4hkazmSekhYZ6jaDeZne`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "05d9a721-a772-44c8-81ad-432e08e0421e",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "b917983f-ab40-4f9f-a426-b9a34c644f01",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-15T15:51:36.635Z_

<details><summary>↩ Tool result · `toolu_01XG4hkazmSekhYZ6jaDeZne`</summary>

```text
1	\section{Introduction}
2	\label{sec:intro}
3	
4	The text on which large language models are trained increasingly contains their own outputs.
5	As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
6	This model$\to$data$\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
7	
8	Existing tools address adjacent but distinct problems.
9	Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
10	Watermarking \cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.
11	The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
12	No existing method estimates the ordinal recursive depth of a text passage from its content alone.
13	
14	Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints exhibit universal stability across model families and decoding strategies.
15	Specifically, perplexity tail statistics---the 90th-percentile perplexity (\textsc{p90\_ppl}) and surprisal variance (\textsc{var\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 7/9 model--strategy configurations, respectively.
16	
17	We formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.
18	Given a text passage, we compute a 19-dimensional feature vector from reference-model perplexity statistics---capturing distributional location, spread, tail behavior, and lexical diversity---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).
19	To systematically characterize how recursive generation reshapes these features, we construct the \emph{Depth Degradation Atlas}: a $3 \times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.
20	The atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.
21	
22	Our contributions are:
23	
24	\begin{itemize}
25	    \item \textbf{Task formalization.} We define recursive generation depth estimation as ordinal classification and introduce the EDD metric, which summarizes the maximum depth at which adjacent generations remain separable above a given AUC threshold.
26	
27	    \item \textbf{Depth Degradation Atlas.} We construct a systematic $3 \times 3$ map across model families and decoding strategies, revealing that \textsc{p90\_ppl} ranks in the top 2 in all 9 cells (100\%) and \textsc{var\_surprisal} in 7/9 (78\%), with a mean Spearman rank correlation of $\rho{=}0.868$ across importance vectors. The extended Pythia nucleus pipeline (d0--d5) yields $\mathrm{EDD}_{0.75}{=}4$, establishing that depth discrimination persists through four recursive steps before falling below threshold.
28	
29	    \item \textbf{Generalization analysis.} Cross-model leave-one-out transfer achieves 66.4\% and cross-strategy transfer 59.1\% (chance = 25\%). We identify a temperature-induced d1/d2 AUC inversion (GPT-2~XL: 0.129, OLMo: 0.253) that z-score normalization cannot resolve, confirming a geometry-level shift.
30	
31	    \item \textbf{End-to-end learning as negative result.} Both DeBERTa-v3-base (58.3\%) and RoBERTa-base (59.5\%) achieve ${\sim}$59\% via end-to-end finetuning---19pp below feature-based classifiers (78.2\%)---with the architecture-invariant gap ruling out model selection bias. Probing reveals significant negative correlations (DeBERTa: $\rho{=}{-}0.48$, RoBERTa: $\rho{=}{-}0.46$) between transformer attention and RF feature importance, confirming complementary representations.
32	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b917983f-ab40-4f9f-a426-b9a34c644f01",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "31ab41d4-93d7-49e9-a89c-60799c1cbc1c",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive depth of a text passage from its content alone.\n\nOur key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints exhibit universal stability across model families and decoding strategies.\nSpecifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 7/9 model--strategy configurations, respectively.\n\nWe formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.\nGiven a text passage, we compute a 19-dimensional feature vector from reference-model perplexity statistics---capturing distributional location, spread, tail behavior, and lexical diversity---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).\nTo systematically characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.\nThe atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\n\\begin{itemize}\n    \\item \\textbf{Task formalization.} We define recursive generation depth estimation as ordinal classification and introduce the EDD metric, which summarizes the maximum depth at which adjacent generations remain separable above a given AUC threshold.\n\n    \\item \\textbf{Depth Degradation Atlas.} We construct a systematic $3 \\times 3$ map across model families and decoding strategies, revealing that \\textsc{p90\\_ppl} ranks in the top 2 in all 9 cells (100\\%) and \\textsc{var\\_surprisal} in 7/9 (78\\%), with a mean Spearman rank correlation of $\\rho{=}0.868$ across importance vectors. The extended Pythia nucleus pipeline (d0--d5) yields $\\mathrm{EDD}_{0.75}{=}4$, establishing that depth discrimination persists through four recursive steps before falling below threshold.\n\n    \\item \\textbf{Generalization analysis.} Cross-model leave-one-out transfer achieves 66.4\\% and cross-strategy transfer 59.1\\% (chance = 25\\%). We identify a temperature-induced d1/d2 AUC inversion (GPT-2~XL: 0.129, OLMo: 0.253) that z-score normalization cannot resolve, confirming a geometry-level shift.\n\n    \\item \\textbf{End-to-end learning as negative result.} Both DeBERTa-v3-base (58.3\\%) and RoBERTa-base (59.5\\%) achieve ${\\sim}$59\\% via end-to-end finetuning---19pp below feature-based classifiers (78.2\\%)---with the architecture-invariant gap ruling out model selection bias. Probing reveals significant negative correlations (DeBERTa: $\\rho{=}{-}0.48$, RoBERTa: $\\rho{=}{-}0.46$) between transformer attention and RF feature importance, confirming complementary representations.\n\\end{itemize}",
      "numLines": 32,
      "startLine": 1,
      "totalLines": 32
    }
  },
  "sourceToolAssistantUUID": "b917983f-ab40-4f9f-a426-b9a34c644f01",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-15T15:51:37.493Z_

<details open><summary>🔧 Tool call — Read · `toolu_011d6cimpdh3FPShhLnnoD3k`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "31ab41d4-93d7-49e9-a89c-60799c1cbc1c",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "12feeb33-0d53-4420-9d88-759e5d545570",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 25 · 2026-05-15T15:51:37.498Z_

<details><summary>↩ Tool result · `toolu_011d6cimpdh3FPShhLnnoD3k`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\paragraph{Model Collapse Theory.}
5	\citet{shumailov2024_nature} demonstrate that recursively training language models on their own outputs erodes distributional tails, eventually collapsing the output distribution to a narrow mode.
6	\citet{dohmatob2024_tale_of_tails} formalize this phenomenon through scaling laws that distinguish tail \emph{narrowing} (reduced variance) from tail \emph{cutting} (lost support), showing both accelerate with generation depth; \citet{dohmatob2024_strong_collapse} establish strong collapse guarantees, and \citet{dohmatob2024_demystified} analyze the regression case.
7	The MAD framework \cite{alemohammad2024_mad} extends this analysis to self-consuming generative models and quantifies the precision--recall tradeoff as synthetic data accumulates across generations.
8	Mitigation strategies include retaining real data \cite{gerstgrasser2024_accumulate} and filtering synthetic samples via detection \cite{drayson2025_detection_prevents_collapse}.
9	Recent work identifies non-monotonic dynamics \cite{bakshi2026_collapse_improvement}, fixed-point convergence \cite{marchi2024_heat_death}, contamination bounds \cite{wang2026_contamination}, curated pipelines \cite{falahati2026_curated}, knowledge collapse \cite{knowledge_collapse2025}, spectral signatures \cite{sigma2026_spectral}, and self-improving loops \cite{synthetic_eggs2026}.
10	These works characterize degradation patterns but assume the generation depth is known a priori; our work addresses the inverse problem of estimating depth from text alone.
11	
12	\paragraph{AI Text Detection.}
13	DetectGPT \cite{mitchell2023_detectgpt} introduced probability curvature---the tendency of model-generated text to occupy local maxima of the log-probability surface---as a zero-shot detection signal.
14	\citet{fast_detectgpt2024} improve computational efficiency by replacing random perturbations with conditional probability curvature from a surrogate model.
15	Binoculars \cite{binoculars2024} exploits the perplexity ratio between two related models, achieving strong detection without training data.
16	DivEye \cite{diveye2026} leverages surprisal diversity patterns, while GLTR \cite{gehrmann2019_gltr} provides statistical visualization of per-token likelihood ranks for human inspection.
17	\citet{sadasivan2023_paraphrase} expose fundamental limits: paraphrasing attacks reduce detection accuracy to near chance, and \citet{pudasaini2026_detection_fails} show detection degrades under distribution shift between training and deployment domains.
18	\citet{pu2026_generator_barrier} formalize a generator barrier bounding detection performance when the generator is unknown.
19	All these methods perform binary classification (human vs.\ machine), discarding the ordinal depth information that distinguishes first-generation from deeply recursive text.
20	Our approach outputs ordinal depth labels, complementing rather than replacing binary detection.
21	
22	\paragraph{Adjacent Tasks.}
23	EditLens \cite{editlens2026} estimates the \emph{extent} of editing applied to a passage---a continuous measure of how much a text has been modified in a single pass---but does not model recursive generation chains.
24	\citet{uchendu2020_attribution} formulate authorship attribution as multi-source classification, identifying \emph{which} model generated a text rather than \emph{how many} recursive steps it has undergone.
25	LOKI \cite{loki2025} provides a comprehensive benchmark spanning multiple synthetic data modalities but evaluates binary detection, not depth estimation.
26	\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, quantifying information distortion across rounds; while their work measures forward degradation fidelity, our task performs the inverse: classifying generation depth from text alone, without access to the generation chain.
27	
28	\paragraph{Decoding Strategy Effects.}
29	The choice of decoding strategy shapes the statistical properties of generated text in ways that interact with generation depth signals.
30	\citet{holtzman2020_nucleus} show that unrestricted sampling produces degenerate repetitions and propose nucleus sampling to maintain output diversity.
31	\citet{finlayson2024_closing} demonstrate that decoding parameters affect downstream evaluation metrics in non-trivial ways.
32	\citet{garces_arias2025_decoding_decoded} find that the effect of decoding strategies on text quality is model-dependent, complicating universal quality claims.
33	\citet{wiher2022_decoding} provide a systematic comparison of decoding methods on surface-level text properties, and Mirostat \cite{basu2021_mirostat} introduces perplexity-controlled decoding that actively regulates output entropy.
34	Our Depth Degradation Atlas (\S\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation---temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal---effects that go beyond single-pass text quality to shape the discriminability of generation depth itself.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "12feeb33-0d53-4420-9d88-759e5d545570",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "cdfb4a73-8a87-492b-bda6-183dc017a638",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Model Collapse Theory.}\n\\citet{shumailov2024_nature} demonstrate that recursively training language models on their own outputs erodes distributional tails, eventually collapsing the output distribution to a narrow mode.\n\\citet{dohmatob2024_tale_of_tails} formalize this phenomenon through scaling laws that distinguish tail \\emph{narrowing} (reduced variance) from tail \\emph{cutting} (lost support), showing both accelerate with generation depth; \\citet{dohmatob2024_strong_collapse} establish strong collapse guarantees, and \\citet{dohmatob2024_demystified} analyze the regression case.\nThe MAD framework \\cite{alemohammad2024_mad} extends this analysis to self-consuming generative models and quantifies the precision--recall tradeoff as synthetic data accumulates across generations.\nMitigation strategies include retaining real data \\cite{gerstgrasser2024_accumulate} and filtering synthetic samples via detection \\cite{drayson2025_detection_prevents_collapse}.\nRecent work identifies non-monotonic dynamics \\cite{bakshi2026_collapse_improvement}, fixed-point convergence \\cite{marchi2024_heat_death}, contamination bounds \\cite{wang2026_contamination}, curated pipelines \\cite{falahati2026_curated}, knowledge collapse \\cite{knowledge_collapse2025}, spectral signatures \\cite{sigma2026_spectral}, and self-improving loops \\cite{synthetic_eggs2026}.\nThese works characterize degradation patterns but assume the generation depth is known a priori; our work addresses the inverse problem of estimating depth from text alone.\n\n\\paragraph{AI Text Detection.}\nDetectGPT \\cite{mitchell2023_detectgpt} introduced probability curvature---the tendency of model-generated text to occupy local maxima of the log-probability surface---as a zero-shot detection signal.\n\\citet{fast_detectgpt2024} improve computational efficiency by replacing random perturbations with conditional probability curvature from a surrogate model.\nBinoculars \\cite{binoculars2024} exploits the perplexity ratio between two related models, achieving strong detection without training data.\nDivEye \\cite{diveye2026} leverages surprisal diversity patterns, while GLTR \\cite{gehrmann2019_gltr} provides statistical visualization of per-token likelihood ranks for human inspection.\n\\citet{sadasivan2023_paraphrase} expose fundamental limits: paraphrasing attacks reduce detection accuracy to near chance, and \\citet{pudasaini2026_detection_fails} show detection degrades under distribution shift between training and deployment domains.\n\\citet{pu2026_generator_barrier} formalize a generator barrier bounding detection performance when the generator is unknown.\nAll these methods perform binary classification (human vs.\\ machine), discarding the ordinal depth information that distinguishes first-generation from deeply recursive text.\nOur approach outputs ordinal depth labels, complementing rather than replacing binary detection.\n\n\\paragraph{Adjacent Tasks.}\nEditLens \\cite{editlens2026} estimates the \\emph{extent} of editing applied to a passage---a continuous measure of how much a text has been modified in a single pass---but does not model recursive generation chains.\n\\citet{uchendu2020_attribution} formulate authorship attribution as multi-source classification, identifying \\emph{which} model generated a text rather than \\emph{how many} recursive steps it has undergone.\nLOKI \\cite{loki2025} provides a comprehensive benchmark spanning multiple synthetic data modalities but evaluates binary detection, not depth estimation.\n\\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, quantifying information distortion across rounds; while their work measures forward degradation fidelity, our task performs the inverse: classifying generation depth from text alone, without access to the generation chain.\n\n\\paragraph{Decoding Strategy Effects.}\nThe choice of decoding strategy shapes the statistical properties of generated text in ways that interact with generation depth signals.\n\\citet{holtzman2020_nucleus} show that unrestricted sampling produces degenerate repetitions and propose nucleus sampling to maintain output diversity.\n\\citet{finlayson2024_closing} demonstrate that decoding parameters affect downstream evaluation metrics in non-trivial ways.\n\\citet{garces_arias2025_decoding_decoded} find that the effect of decoding strategies on text quality is model-dependent, complicating universal quality claims.\n\\citet{wiher2022_decoding} provide a systematic comparison of decoding methods on surface-level text properties, and Mirostat \\cite{basu2021_mirostat} introduces perplexity-controlled decoding that actively regulates output entropy.\nOur Depth Degradation Atlas (\\S\\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation---temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal---effects that go beyond single-pass text quality to shape the discriminability of generation depth itself.",
      "numLines": 34,
      "startLine": 1,
      "totalLines": 34
    }
  },
  "sourceToolAssistantUUID": "12feeb33-0d53-4420-9d88-759e5d545570",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-15T15:51:37.965Z_

<details open><summary>🔧 Tool call — Read · `toolu_01TfHTKrAPcrWJ2xcXdYkvw8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cdfb4a73-8a87-492b-bda6-183dc017a638",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "d48e766c-4c77-4fab-a921-b986fe1b8e28",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 27 · 2026-05-15T15:51:37.975Z_

<details><summary>↩ Tool result · `toolu_01TfHTKrAPcrWJ2xcXdYkvw8`</summary>

```text
1	\section{Task Formulation}
2	\label{sec:method}
3	
4	\subsection{Problem Definition}
5	\label{sec:method:problem}
6	
7	Let $f_\theta$ denote a language model and $\mathcal{D}_0$ a corpus of human-written seed text.
8	We define a \emph{recursive generation chain} of depth $K$ as the sequence $\mathcal{D}_0, \mathcal{D}_1, \dots, \mathcal{D}_K$, where each $\mathcal{D}_k$ ($k \geq 1$) is produced by finetuning $f_\theta$ on $\mathcal{D}_{k-1}$ and sampling from the resulting model.
9	Depth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.
10	
11	Given a text passage $x$, the task is to estimate its recursive generation depth $d \in \{0, 1, \dots, K\}$.
12	This is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.
13	
14	\subsection{Multi-Generational Benchmark Construction}
15	\label{sec:method:benchmark}
16	
17	We construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.
18	
19	\paragraph{Model families.}
20	We select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).
21	Restricting to a narrow parameter range isolates the effect of architecture and training data from scale.
22	
23	\paragraph{Decoding strategies.}
24	Each model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \cite{holtzman2020_nucleus}, temperature sampling ($\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).
25	These span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.
26	
27	\paragraph{Depth and scale.}
28	The primary benchmark covers depths d0--d3 across all $3 \times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).
29	For depth extension experiments (\S\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.
30	
31	\paragraph{Generation pipeline.}
32	Starting from a Wikipedia subset as seed text ($\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \cite{hu2022lora} with rank $r{=}16$, $\alpha{=}32$, learning rate $2{\times}10^{-4}$, batch size 8, for 3 epochs; (2)~generation of 5{,}000 passages (max 512 tokens) under the specified decoding strategy; (3)~the generated corpus becomes $\mathcal{D}_k$ and serves as training data for the next cycle.
33	Each generation cycle samples unconditionally from the BOS token; there is no per-passage lineage across depths, ensuring that cross-validation splits do not introduce information leakage.
34	LoRA targets are architecture-specific: \texttt{query\_key\_value} for Pythia (GPT-NeoX), \texttt{q\_proj}/\texttt{k\_proj}/\texttt{v\_proj} for OLMo, and \texttt{c\_attn}/\texttt{c\_proj} for GPT-2~XL.
35	We adopt standard LoRA hyperparameters ($r{=}16$, $\alpha{=}32$, dropout$\,{=}\,0.05$) following \citet{hu2022lora}, applied uniformly across all models.
36	
37	\paragraph{Reference model.}
38	All statistical features (\S\ref{sec:method:features}) are computed using a fixed reference model---GPT-2 base (124M)---that is independent of the three generation models.
39	The reference model computes per-token perplexity for each passage, providing a consistent measurement frame across model families.
40	In cross-model leave-one-out evaluation (\S\ref{sec:generalization}), the reference model remains fixed even when GPT-2~XL is held out; the partial architectural overlap this introduces is discussed in Limitations.
41	
42	\subsection{Statistical Feature Design}
43	\label{sec:method:features}
44	
45	We extract a 19-dimensional feature vector $\mathbf{f}(x)$ from the reference-model perplexity distribution over each passage $x$.
46	The features fall into four categories (Table~\ref{tab:features}).
47	
48	\begin{table}[t]
49	\centering
50	\small
51	\caption{The 19 statistical features comprising $\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (GPT-2 base, 124M).}
52	\label{tab:features}
53	\begin{tabular}{@{}llr@{}}
54	\toprule
55	Category & Features & $n$ \\
56	\midrule
57	Perplexity & mean, var, skewness, kurtosis, & 9 \\
58	statistics & p10, p25, p50, p75, p90 & \\
59	\addlinespace
60	Surprisal & mean, var, entropy & 3 \\
61	statistics & & \\
62	\addlinespace
63	Lexical & type--token ratio, hapax ratio, & 4 \\
64	diversity & bigram entropy, trigram entropy & \\
65	\addlinespace
66	Repetition & repeated 2/3/4-gram fractions & 3 \\
67	\bottomrule
68	\end{tabular}
69	\end{table}
70	
71	\emph{Perplexity statistics} (9 features) capture the location, spread, and shape of the per-token perplexity distribution via its mean, variance, skewness, kurtosis, and five percentile quantiles (p10--p90).
72	The tail quantiles (p75, p90) prove especially informative: recursive finetuning erodes the high-perplexity tail, making these features monotonically decreasing with depth (\S\ref{sec:atlas}).
73	
74	\emph{Surprisal statistics} (3 features) operate on $-\log p(\text{token})$ and include mean surprisal, surprisal variance, and the entropy of the surprisal distribution.
75	While correlated with perplexity features, surprisal variance captures second-order structure---the variability of token predictability---that is not redundant with perplexity moments.
76	
77	\emph{Lexical diversity} (4 features) measures vocabulary usage through type--token ratio, hapax ratio (fraction of tokens appearing exactly once), and bigram/trigram entropy.
78	
79	\emph{Repetition} (3 features) quantifies the fraction of repeated $n$-grams for $n \in \{2, 3, 4\}$, capturing the increased self-repetition characteristic of recursive generation.
80	
81	\subsection{Effective Discriminable Depth}
82	\label{sec:method:edd}
83	
84	Aggregate classification accuracy over $K{+}1$ classes obscures whether discriminability degrades at specific depths.
85	We introduce the \emph{Effective Discriminable Depth} (EDD), a scalar metric that summarizes how far into a recursive chain adjacent depths remain distinguishable.
86	
87	For each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary Random Forest (500 trees; increased from 200 in the multi-class setting to ensure convergence on the smaller per-pair samples) and compute the one-vs-one AUC.
88	Given a threshold $T$, we define:
89	\begin{equation}
90	\mathrm{EDD}_T = \max \{ d^*{+}1 : \mathrm{AUC}(d^*, d^*{+}1) \geq T \}
91	\label{eq:edd}
92	\end{equation}
93	where $d^* \in \{0, 1, \dots, K{-}1\}$.
94	The default threshold is $T{=}0.75$; we report sensitivity analyses at $T \in \{0.65, 0.70, 0.75, 0.80\}$ in \S\ref{sec:atlas}.
95	Crucially, each AUC is obtained from an independent binary pairwise classifier (5-fold stratified CV) rather than extracted from a single multi-class model, avoiding decision boundary dilution (\S\ref{sec:atlas}).
96	
97	EDD captures a natural question: \emph{how deep into the recursive chain can we reliably distinguish successive generations?}
98	A high EDD indicates that the statistical fingerprints retain discriminative power across many recursion steps; a low EDD signals rapid convergence to an indistinguishable regime.
99	
100	\paragraph{Classifiers.}
101	Our primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).
102	We compare against CORAL ordinal regression \cite{coral2020}, DivEye \cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \S\ref{sec:generalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d48e766c-4c77-4fab-a921-b986fe1b8e28",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "90050985-10e5-4d0f-941b-29b6855fb46d",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "content": "\\section{Task Formulation}\n\\label{sec:method}\n\n\\subsection{Problem Definition}\n\\label{sec:method:problem}\n\nLet $f_\\theta$ denote a language model and $\\mathcal{D}_0$ a corpus of human-written seed text.\nWe define a \\emph{recursive generation chain} of depth $K$ as the sequence $\\mathcal{D}_0, \\mathcal{D}_1, \\dots, \\mathcal{D}_K$, where each $\\mathcal{D}_k$ ($k \\geq 1$) is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$ and sampling from the resulting model.\nDepth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \\geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.\n\nGiven a text passage $x$, the task is to estimate its recursive generation depth $d \\in \\{0, 1, \\dots, K\\}$.\nThis is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.\n\n\\subsection{Multi-Generational Benchmark Construction}\n\\label{sec:method:benchmark}\n\nWe construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.\n\n\\paragraph{Model families.}\nWe select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).\nRestricting to a narrow parameter range isolates the effect of architecture and training data from scale.\n\n\\paragraph{Decoding strategies.}\nEach model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\nThese span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.\n\n\\paragraph{Depth and scale.}\nThe primary benchmark covers depths d0--d3 across all $3 \\times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).\nFor depth extension experiments (\\S\\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.\n\n\\paragraph{Generation pipeline.}\nStarting from a Wikipedia subset as seed text ($\\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \\cite{hu2022lora} with rank $r{=}16$, $\\alpha{=}32$, learning rate $2{\\times}10^{-4}$, batch size 8, for 3 epochs; (2)~generation of 5{,}000 passages (max 512 tokens) under the specified decoding strategy; (3)~the generated corpus becomes $\\mathcal{D}_k$ and serves as training data for the next cycle.\nEach generation cycle samples unconditionally from the BOS token; there is no per-passage lineage across depths, ensuring that cross-validation splits do not introduce information leakage.\nLoRA targets are architecture-specific: \\texttt{query\\_key\\_value} for Pythia (GPT-NeoX), \\texttt{q\\_proj}/\\texttt{k\\_proj}/\\texttt{v\\_proj} for OLMo, and \\texttt{c\\_attn}/\\texttt{c\\_proj} for GPT-2~XL.\nWe adopt standard LoRA hyperparameters ($r{=}16$, $\\alpha{=}32$, dropout$\\,{=}\\,0.05$) following \\citet{hu2022lora}, applied uniformly across all models.\n\n\\paragraph{Reference model.}\nAll statistical features (\\S\\ref{sec:method:features}) are computed using a fixed reference model---GPT-2 base (124M)---that is independent of the three generation models.\nThe reference model computes per-token perplexity for each passage, providing a consistent measurement frame across model families.\nIn cross-model leave-one-out evaluation (\\S\\ref{sec:generalization}), the reference model remains fixed even when GPT-2~XL is held out; the partial architectural overlap this introduces is discussed in Limitations.\n\n\\subsection{Statistical Feature Design}\n\\label{sec:method:features}\n\nWe extract a 19-dimensional feature vector $\\mathbf{f}(x)$ from the reference-model perplexity distribution over each passage $x$.\nThe features fall into four categories (Table~\\ref{tab:features}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{The 19 statistical features comprising $\\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (GPT-2 base, 124M).}\n\\label{tab:features}\n\\begin{tabular}{@{}llr@{}}\n\\toprule\nCategory & Features & $n$ \\\\\n\\midrule\nPerplexity & mean, var, skewness, kurtosis, & 9 \\\\\nstatistics & p10, p25, p50, p75, p90 & \\\\\n\\addlinespace\nSurprisal & mean, var, entropy & 3 \\\\\nstatistics & & \\\\\n\\addlinespace\nLexical & type--token ratio, hapax ratio, & 4 \\\\\ndiversity & bigram entropy, trigram entropy & \\\\\n\\addlinespace\nRepetition & repeated 2/3/4-gram fractions & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\emph{Perplexity statistics} (9 features) capture the location, spread, and shape of the per-token perplexity distribution via its mean, variance, skewness, kurtosis, and five percentile quantiles (p10--p90).\nThe tail quantiles (p75, p90) prove especially informative: recursive finetuning erodes the high-perplexity tail, making these features monotonically decreasing with depth (\\S\\ref{sec:atlas}).\n\n\\emph{Surprisal statistics} (3 features) operate on $-\\log p(\\text{token})$ and include mean surprisal, surprisal variance, and the entropy of the surprisal distribution.\nWhile correlated with perplexity features, surprisal variance captures second-order structure---the variability of token predictability---that is not redundant with perplexity moments.\n\n\\emph{Lexical diversity} (4 features) measures vocabulary usage through type--token ratio, hapax ratio (fraction of tokens appearing exactly once), and bigram/trigram entropy.\n\n\\emph{Repetition} (3 features) quantifies the fraction of repeated $n$-grams for $n \\in \\{2, 3, 4\\}$, capturing the increased self-repetition characteristic of recursive generation.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:method:edd}\n\nAggregate classification accuracy over $K{+}1$ classes obscures whether discriminability degrades at specific depths.\nWe introduce the \\emph{Effective Discriminable Depth} (EDD), a scalar metric that summarizes how far into a recursive chain adjacent depths remain distinguishable.\n\nFor each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary Random Forest (500 trees; increased from 200 in the multi-class setting to ensure convergence on the smaller per-pair samples) and compute the one-vs-one AUC.\nGiven a threshold $T$, we define:\n\\begin{equation}\n\\mathrm{EDD}_T = \\max \\{ d^*{+}1 : \\mathrm{AUC}(d^*, d^*{+}1) \\geq T \\}\n\\label{eq:edd}\n\\end{equation}\nwhere $d^* \\in \\{0, 1, \\dots, K{-}1\\}$.\nThe default threshold is $T{=}0.75$; we report sensitivity analyses at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ in \\S\\ref{sec:atlas}.\nCrucially, each AUC is obtained from an independent binary pairwise classifier (5-fold stratified CV) rather than extracted from a single multi-class model, avoiding decision boundary dilution (\\S\\ref{sec:atlas}).\n\nEDD captures a natural question: \\emph{how deep into the recursive chain can we reliably distinguish successive generations?}\nA high EDD indicates that the statistical fingerprints retain discriminative power across many recursion steps; a low EDD signals rapid convergence to an indistinguishable regime.\n\n\\paragraph{Classifiers.}\nOur primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).\nWe compare against CORAL ordinal regression \\cite{coral2020}, DivEye \\cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \\S\\ref{sec:generalization}.",
      "numLines": 102,
      "startLine": 1,
      "totalLines": 102
    }
  },
  "sourceToolAssistantUUID": "d48e766c-4c77-4fab-a921-b986fe1b8e28",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-15T15:51:38.430Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NDxMQieEB7gwXum2HpaqBr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "90050985-10e5-4d0f-941b-29b6855fb46d",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "b2e89ce1-63f1-4c6b-a623-9664945c6af3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 29 · 2026-05-15T15:51:38.435Z_

<details><summary>↩ Tool result · `toolu_01NDxMQieEB7gwXum2HpaqBr`</summary>

```text
1	\section{The Depth Degradation Atlas}
2	\label{sec:atlas}
3	
4	We systematically characterize how recursive generation reshapes the statistical profile of text across a grid of 3 model families $\times$ 3 decoding strategies $\times$ 4 generation depths (d0--d3), yielding 9 experimental configurations each spanning 4 depths.
5	For each cell we train a Random Forest (RF) classifier on the 19 statistical features defined in \S\ref{sec:method} and examine (i)~in-distribution depth classification accuracy, (ii)~which features carry depth signal, (iii)~how far into the recursion chain depth remains discriminable, and (iv)~how decoding strategy modulates the degradation trajectory.
6	
7	\subsection{In-Distribution Performance}
8	\label{sec:atlas:indist}
9	
10	Table~\ref{tab:main_matrix} reports 4-class depth estimation accuracy under 5-fold cross-validation.
11	All 9 cells exceed chance (25\%) by a wide margin, with accuracy ranging from 69.6\% to 85.4\%.
12	Both model family and decoding strategy influence accuracy, with model ordering GPT-2~XL $>$ OLMo $>$ Pythia holding across all strategies.
13	Top-$k$ ($k{=}50$) trails by 6--9 percentage points, while temperature and nucleus sampling alternate for the lead depending on model family.
14	
15	\begin{table}[t]
16	\centering
17	\small
18	\caption{In-distribution 4-class depth estimation accuracy (\%) across 3 model families $\times$ 3 decoding strategies. RF classifier with 19 statistical features, 5-fold CV (std 0.2--0.9pp across all cells). Chance = 25\%.}
19	\label{tab:main_matrix}
20	\begin{tabular}{lccc}
21	\toprule
22	Model & Nucleus & Temp & Top-$k$ \\
23	 & $p{=}0.95$ & $\tau{=}0.9$ & $k{=}50$ \\
24	\midrule
25	Pythia-1.4B & 78.2 & 76.3 & 69.6 \\
26	OLMo-1B & 78.8 & 82.0 & 74.2 \\
27	GPT-2 XL & 83.3 & \textbf{85.4} & 76.6 \\
28	\bottomrule
29	\end{tabular}
30	\end{table}
31	
32	Because the human-written seed text (d0) is often trivially separable from any machine-generated depth, we also evaluate 3-class accuracy excluding d0.
33	Performance drops moderately---GPT-2~XL with temperature sampling still reaches 82.0\%, and even the weakest setting (Pythia nucleus) retains 70.8\%---confirming that the classifier captures inter-generation differences beyond the human--machine boundary.
34	
35	\subsection{Feature Universality}
36	\label{sec:atlas:features}
37	
38	To identify which statistical fingerprints carry depth signal, we train a dedicated binary RF per cell (d$_i$ vs.\ rest) and extract feature importances (Gini impurity; permutation importance yields consistent rankings, Appendix~\ref{app:permutation}).
39	Figure~\ref{fig:atlas_heatmap} visualizes the top-7 feature importances across all 9 cells.
40	
41	Two features dominate.
42	The 90th-percentile perplexity (\textsc{p90\_ppl}) ranks in the top 2 in all 9 cells, while surprisal variance (\textsc{var\_surprisal}) does so in 7 of 9.
43	In the two exceptions---GPT-2~XL with temperature and top-$k$ sampling---the 75th-percentile perplexity (\textsc{p75\_ppl}) replaces surprisal variance in the top 2, though surprisal variance remains among the top 4 features.
44	To quantify cross-model agreement, we compute the Spearman rank correlation of the full 19-feature importance vectors across all $\binom{9}{2}=36$ cell pairs and obtain a mean $\rho = 0.868$ (range: 0.619--0.954).
45	
46	\begin{figure}[t]
47	\centering
48	\includegraphics[width=\columnwidth]{../../figures/paper/fig_atlas_heatmap.pdf}
49	\caption{Feature importance heatmap across 9 cells (3 models $\times$ 3 strategies). Top-7 features by mean importance. \textsc{p90\_ppl} appears in the top 2 for all cells; \textsc{var\_surprisal} for 7 of 9.}
50	\label{fig:atlas_heatmap}
51	\end{figure}
52	
53	These results align with theoretical predictions: recursive finetuning erodes the tail of the token-probability distribution \cite{shumailov2024_nature,dohmatob2024_tale_of_tails}, and high-percentile perplexity directly measures tail behavior.
54	The universality of these markers across architectures and decoding strategies suggests they reflect a structural property of the recursive generation process rather than model-specific artifacts.
55	
56	\subsection{Effective Discriminable Depth}
57	\label{sec:atlas:edd}
58	
59	Aggregate accuracy masks that adjacent depths become harder to distinguish as depth increases; we quantify this via the \emph{Effective Discriminable Depth} (EDD).
60	For each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary RF (500 trees, 5-fold stratified CV) and compute $\mathrm{AUC}(d, d{+}1)$ (Eq.~\ref{eq:edd}).
61	We set $T{=}0.75$ as the default threshold---the midpoint between chance AUC (0.5) and perfect discrimination (1.0)---and report sensitivity at $T \in \{0.65, 0.70, 0.75, 0.80\}$ below.
62	
63	Within the 4-class atlas (d0--d3), 7 of 9 cells achieve $\mathrm{EDD}_{0.75}=3$; the two exceptions are Pythia and OLMo with top-$k$ sampling ($\mathrm{EDD}_{0.75}=2$), consistent with top-$k$'s signal-attenuating effect noted in \S\ref{sec:atlas:indist}.
64	
65	We extend the Pythia-1.4B nucleus pipeline to 6 depths (d0--d5) and train a 500-tree binary RF for each adjacent pair.
66	Figure~\ref{fig:auc_decay} shows the pairwise AUC decay curve.
67	The d0\,vs.\,d1 boundary is near-perfect (AUC\,=\,0.998), reflecting the well-known human--machine gap.
68	Subsequent boundaries degrade monotonically: d1\,vs.\,d2 achieves 0.925 [95\% CI: 0.914,\,0.935], d2\,vs.\,d3 reaches 0.823 [0.805,\,0.840], and d3\,vs.\,d4 yields 0.784 [0.765,\,0.802]---with the confidence interval lower bound still exceeding $T{=}0.75$.
69	At d4\,vs.\,d5, AUC drops to 0.683 [0.661,\,0.705], falling below the threshold and fixing $\mathrm{EDD}_{0.75}=4$.
70	
71	\paragraph{Cross-model EDD.}
72	We extend the same d0--d5 pipeline to OLMo-1B and GPT-2~XL (both nucleus $p{=}0.95$).
73	The d3\,vs.\,d4 AUC consistently clusters near the 0.75 threshold: Pythia 0.784 ($p{=}0.001$), OLMo 0.765 ($p{=}0.091$, marginal), GPT-2~XL 0.750 ($p{=}0.505$, n.s.)---only Pythia achieves conventional significance, yet all three exhibit the same directional pattern.
74	At d4\,vs.\,d5, AUC uniformly drops below 0.70 (Pythia 0.683, OLMo 0.684, GPT-2~XL 0.681), fixing $\mathrm{EDD}_{0.75}{=}4$ for all three models.
75	This cross-model EDD is stable across threshold choices: all three yield $\mathrm{EDD}{=}5$ at $T{=}0.65$, $\mathrm{EDD}{=}4$ at $T \in \{0.70, 0.75\}$, and $\mathrm{EDD}{=}3$ at $T{=}0.80$, matching the single-model pattern in Table~\ref{tab:edd_sensitivity}.
76	
77	\begin{figure}[t]
78	\centering
79	\includegraphics[width=\columnwidth]{../../figures/paper/fig_auc_decay.pdf}
80	\caption{Binary pairwise AUC between adjacent depths (Pythia-1.4B, nucleus $p{=}0.95$, d0--d5). Shaded bands: 95\% bootstrap CI. Dashed line: $T{=}0.75$. $\mathrm{EDD}_{0.75}=4$: depth pairs up to d3\,vs.\,d4 remain discriminable.}
81	\label{fig:auc_decay}
82	\end{figure}
83	
84	Table~\ref{tab:edd_sensitivity} shows the sensitivity of EDD to the choice of threshold.
85	At $T{=}0.65$, all pairs through d4\,vs.\,d5 pass, giving $\mathrm{EDD}=5$.
86	At $T{=}0.80$, only d1\,vs.\,d2 and d2\,vs.\,d3 pass, yielding $\mathrm{EDD}=3$.
87	The d0\,vs.\,d1 pair passes at every threshold ($\text{AUC}\geq0.99$).
88	
89	\begin{table}[t]
90	\centering
91	\small
92	\caption{EDD sensitivity to threshold $T$ (Pythia-1.4B, nucleus $p{=}0.95$). \checkmark: pairwise AUC $\geq T$; ---: below $T$. d0\,vs.\,d1 always passes (AUC$\geq$0.99) and is omitted.}
93	\label{tab:edd_sensitivity}
94	\begin{tabular}{cccccr}
95	\toprule
96	$T$ & d1/d2 & d2/d3 & d3/d4 & d4/d5 & EDD \\
97	\midrule
98	0.65 & \checkmark & \checkmark & \checkmark & \checkmark & 5 \\
99	0.70 & \checkmark & \checkmark & \checkmark & --- & 4 \\
100	0.75 & \checkmark & \checkmark & \checkmark & --- & 4 \\
101	0.80 & \checkmark & \checkmark & --- & --- & 3 \\
102	\bottomrule
103	\end{tabular}
104	\end{table}
105	
106	\paragraph{Granularity ablation.}
107	Decision boundary dilution motivates EDD's binary-pair design: mean accuracy drops from 99.5\% (binary) to 78.3\% (4-class) to 62.9\% (6-class), and the d2\,vs.\,d3 AUC falls from 0.804 to 0.689 between the 4-class and 6-class settings for Pythia nucleus---a 14\% relative decline attributable to boundary dilution, not signal loss.
108	
109	\subsection{Strategy-Dependent Trajectories}
110	\label{sec:atlas:trajectories}
111	
112	The atlas reveals that decoding strategy does not merely scale the overall signal strength---it reshapes the degradation trajectory.
113	Figure~\ref{fig:feature_trajectory} plots normalized feature means across depths for three key features.
114	
115	\begin{figure}[t]
116	\centering
117	\includegraphics[width=\columnwidth]{../../figures/paper/fig_feature_trajectory.pdf}
118	\caption{Normalized feature trajectories across generation depths for 3 models $\times$ 2 strategies (nucleus $p{=}0.95$, temperature $\tau{=}0.9$). All features decrease monotonically with depth, but inter-depth spacing is highly non-uniform. Top-$k$ results are provided in Appendix~\ref{app:topk_trajectories}.}
119	\label{fig:feature_trajectory}
120	\end{figure}
121	
122	\paragraph{Non-uniform inter-depth spacing.}
123	For Pythia nucleus, \textsc{p90\_ppl} drops from 483.7 (d0) to 61.4 (d1)---an 87\% reduction---but only from 29.7 (d2) to 18.2 (d3), a 39\% reduction.
124	This geometric compression of the feature space explains why adjacent-pair AUC decays monotonically (Figure~\ref{fig:auc_decay}): each successive generation step yields diminishing statistical displacement.
125	
126	\paragraph{Temperature-induced acceleration.}
127	Temperature sampling ($\tau{=}0.9$) applies uniform logit scaling rather than the hard truncation of nucleus or top-$k$, which accelerates convergence toward the low-entropy attractor described by \citet{marchi2024_heat_death}.
128	Concretely, feature values at depth $N$ under temperature sampling approximate those at depth $N{+}1$ under nucleus or top-$k$.
129	This shift yields higher in-distribution accuracy (Table~\ref{tab:main_matrix}) because each depth occupies a more distinct region of feature space, but it also means the d1/d2 boundary under temperature is closer to the d2/d3 boundary under nucleus---a mismatch that creates reversal risk in cross-strategy transfer (\S\ref{sec:generalization}).
130	
131	\paragraph{Three-tier strategy taxonomy.}
132	The trajectory data suggests a functional classification.
133	Nucleus sampling ($p{=}0.95$) serves as a stable baseline with moderate signal strength.
134	Temperature sampling ($\tau{=}0.9$) enhances the signal via accelerated convergence, yielding higher within-strategy accuracy but strategy-specific depth boundaries.
135	Top-$k$ sampling ($k{=}50$) attenuates the signal---accuracy drops 6--9 points relative to nucleus---because hard truncation at a fixed vocabulary size preserves more of the original distribution's shape across depths, compressing inter-depth distances.
136	Notably, top-$k$ preserves the \emph{direction} of all feature trends despite the magnitude reduction, which has implications for ordinal classifiers that rely on monotonicity (\S\ref{sec:generalization}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b2e89ce1-63f1-4c6b-a623-9664945c6af3",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "dd047587-ac16-428d-a938-022f78c08208",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "content": "\\section{The Depth Degradation Atlas}\n\\label{sec:atlas}\n\nWe systematically characterize how recursive generation reshapes the statistical profile of text across a grid of 3 model families $\\times$ 3 decoding strategies $\\times$ 4 generation depths (d0--d3), yielding 9 experimental configurations each spanning 4 depths.\nFor each cell we train a Random Forest (RF) classifier on the 19 statistical features defined in \\S\\ref{sec:method} and examine (i)~in-distribution depth classification accuracy, (ii)~which features carry depth signal, (iii)~how far into the recursion chain depth remains discriminable, and (iv)~how decoding strategy modulates the degradation trajectory.\n\n\\subsection{In-Distribution Performance}\n\\label{sec:atlas:indist}\n\nTable~\\ref{tab:main_matrix} reports 4-class depth estimation accuracy under 5-fold cross-validation.\nAll 9 cells exceed chance (25\\%) by a wide margin, with accuracy ranging from 69.6\\% to 85.4\\%.\nBoth model family and decoding strategy influence accuracy, with model ordering GPT-2~XL $>$ OLMo $>$ Pythia holding across all strategies.\nTop-$k$ ($k{=}50$) trails by 6--9 percentage points, while temperature and nucleus sampling alternate for the lead depending on model family.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{In-distribution 4-class depth estimation accuracy (\\%) across 3 model families $\\times$ 3 decoding strategies. RF classifier with 19 statistical features, 5-fold CV (std 0.2--0.9pp across all cells). Chance = 25\\%.}\n\\label{tab:main_matrix}\n\\begin{tabular}{lccc}\n\\toprule\nModel & Nucleus & Temp & Top-$k$ \\\\\n & $p{=}0.95$ & $\\tau{=}0.9$ & $k{=}50$ \\\\\n\\midrule\nPythia-1.4B & 78.2 & 76.3 & 69.6 \\\\\nOLMo-1B & 78.8 & 82.0 & 74.2 \\\\\nGPT-2 XL & 83.3 & \\textbf{85.4} & 76.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nBecause the human-written seed text (d0) is often trivially separable from any machine-generated depth, we also evaluate 3-class accuracy excluding d0.\nPerformance drops moderately---GPT-2~XL with temperature sampling still reaches 82.0\\%, and even the weakest setting (Pythia nucleus) retains 70.8\\%---confirming that the classifier captures inter-generation differences beyond the human--machine boundary.\n\n\\subsection{Feature Universality}\n\\label{sec:atlas:features}\n\nTo identify which statistical fingerprints carry depth signal, we train a dedicated binary RF per cell (d$_i$ vs.\\ rest) and extract feature importances (Gini impurity; permutation importance yields consistent rankings, Appendix~\\ref{app:permutation}).\nFigure~\\ref{fig:atlas_heatmap} visualizes the top-7 feature importances across all 9 cells.\n\nTwo features dominate.\nThe 90th-percentile perplexity (\\textsc{p90\\_ppl}) ranks in the top 2 in all 9 cells, while surprisal variance (\\textsc{var\\_surprisal}) does so in 7 of 9.\nIn the two exceptions---GPT-2~XL with temperature and top-$k$ sampling---the 75th-percentile perplexity (\\textsc{p75\\_ppl}) replaces surprisal variance in the top 2, though surprisal variance remains among the top 4 features.\nTo quantify cross-model agreement, we compute the Spearman rank correlation of the full 19-feature importance vectors across all $\\binom{9}{2}=36$ cell pairs and obtain a mean $\\rho = 0.868$ (range: 0.619--0.954).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_atlas_heatmap.pdf}\n\\caption{Feature importance heatmap across 9 cells (3 models $\\times$ 3 strategies). Top-7 features by mean importance. \\textsc{p90\\_ppl} appears in the top 2 for all cells; \\textsc{var\\_surprisal} for 7 of 9.}\n\\label{fig:atlas_heatmap}\n\\end{figure}\n\nThese results align with theoretical predictions: recursive finetuning erodes the tail of the token-probability distribution \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails}, and high-percentile perplexity directly measures tail behavior.\nThe universality of these markers across architectures and decoding strategies suggests they reflect a structural property of the recursive generation process rather than model-specific artifacts.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:atlas:edd}\n\nAggregate accuracy masks that adjacent depths become harder to distinguish as depth increases; we quantify this via the \\emph{Effective Discriminable Depth} (EDD).\nFor each adjacent depth pair $(d, d{+}1)$, we train a dedicated binary RF (500 trees, 5-fold stratified CV) and compute $\\mathrm{AUC}(d, d{+}1)$ (Eq.~\\ref{eq:edd}).\nWe set $T{=}0.75$ as the default threshold---the midpoint between chance AUC (0.5) and perfect discrimination (1.0)---and report sensitivity at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ below.\n\nWithin the 4-class atlas (d0--d3), 7 of 9 cells achieve $\\mathrm{EDD}_{0.75}=3$; the two exceptions are Pythia and OLMo with top-$k$ sampling ($\\mathrm{EDD}_{0.75}=2$), consistent with top-$k$'s signal-attenuating effect noted in \\S\\ref{sec:atlas:indist}.\n\nWe extend the Pythia-1.4B nucleus pipeline to 6 depths (d0--d5) and train a 500-tree binary RF for each adjacent pair.\nFigure~\\ref{fig:auc_decay} shows the pairwise AUC decay curve.\nThe d0\\,vs.\\,d1 boundary is near-perfect (AUC\\,=\\,0.998), reflecting the well-known human--machine gap.\nSubsequent boundaries degrade monotonically: d1\\,vs.\\,d2 achieves 0.925 [95\\% CI: 0.914,\\,0.935], d2\\,vs.\\,d3 reaches 0.823 [0.805,\\,0.840], and d3\\,vs.\\,d4 yields 0.784 [0.765,\\,0.802]---with the confidence interval lower bound still exceeding $T{=}0.75$.\nAt d4\\,vs.\\,d5, AUC drops to 0.683 [0.661,\\,0.705], falling below the threshold and fixing $\\mathrm{EDD}_{0.75}=4$.\n\n\\paragraph{Cross-model EDD.}\nWe extend the same d0--d5 pipeline to OLMo-1B and GPT-2~XL (both nucleus $p{=}0.95$).\nThe d3\\,vs.\\,d4 AUC consistently clusters near the 0.75 threshold: Pythia 0.784 ($p{=}0.001$), OLMo 0.765 ($p{=}0.091$, marginal), GPT-2~XL 0.750 ($p{=}0.505$, n.s.)---only Pythia achieves conventional significance, yet all three exhibit the same directional pattern.\nAt d4\\,vs.\\,d5, AUC uniformly drops below 0.70 (Pythia 0.683, OLMo 0.684, GPT-2~XL 0.681), fixing $\\mathrm{EDD}_{0.75}{=}4$ for all three models.\nThis cross-model EDD is stable across threshold choices: all three yield $\\mathrm{EDD}{=}5$ at $T{=}0.65$, $\\mathrm{EDD}{=}4$ at $T \\in \\{0.70, 0.75\\}$, and $\\mathrm{EDD}{=}3$ at $T{=}0.80$, matching the single-model pattern in Table~\\ref{tab:edd_sensitivity}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_auc_decay.pdf}\n\\caption{Binary pairwise AUC between adjacent depths (Pythia-1.4B, nucleus $p{=}0.95$, d0--d5). Shaded bands: 95\\% bootstrap CI. Dashed line: $T{=}0.75$. $\\mathrm{EDD}_{0.75}=4$: depth pairs up to d3\\,vs.\\,d4 remain discriminable.}\n\\label{fig:auc_decay}\n\\end{figure}\n\nTable~\\ref{tab:edd_sensitivity} shows the sensitivity of EDD to the choice of threshold.\nAt $T{=}0.65$, all pairs through d4\\,vs.\\,d5 pass, giving $\\mathrm{EDD}=5$.\nAt $T{=}0.80$, only d1\\,vs.\\,d2 and d2\\,vs.\\,d3 pass, yielding $\\mathrm{EDD}=3$.\nThe d0\\,vs.\\,d1 pair passes at every threshold ($\\text{AUC}\\geq0.99$).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{EDD sensitivity to threshold $T$ (Pythia-1.4B, nucleus $p{=}0.95$). \\checkmark: pairwise AUC $\\geq T$; ---: below $T$. d0\\,vs.\\,d1 always passes (AUC$\\geq$0.99) and is omitted.}\n\\label{tab:edd_sensitivity}\n\\begin{tabular}{cccccr}\n\\toprule\n$T$ & d1/d2 & d2/d3 & d3/d4 & d4/d5 & EDD \\\\\n\\midrule\n0.65 & \\checkmark & \\checkmark & \\checkmark & \\checkmark & 5 \\\\\n0.70 & \\checkmark & \\checkmark & \\checkmark & --- & 4 \\\\\n0.75 & \\checkmark & \\checkmark & \\checkmark & --- & 4 \\\\\n0.80 & \\checkmark & \\checkmark & --- & --- & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Granularity ablation.}\nDecision boundary dilution motivates EDD's binary-pair design: mean accuracy drops from 99.5\\% (binary) to 78.3\\% (4-class) to 62.9\\% (6-class), and the d2\\,vs.\\,d3 AUC falls from 0.804 to 0.689 between the 4-class and 6-class settings for Pythia nucleus---a 14\\% relative decline attributable to boundary dilution, not signal loss.\n\n\\subsection{Strategy-Dependent Trajectories}\n\\label{sec:atlas:trajectories}\n\nThe atlas reveals that decoding strategy does not merely scale the overall signal strength---it reshapes the degradation trajectory.\nFigure~\\ref{fig:feature_trajectory} plots normalized feature means across depths for three key features.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_feature_trajectory.pdf}\n\\caption{Normalized feature trajectories across generation depths for 3 models $\\times$ 2 strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$). All features decrease monotonically with depth, but inter-depth spacing is highly non-uniform. Top-$k$ results are provided in Appendix~\\ref{app:topk_trajectories}.}\n\\label{fig:feature_trajectory}\n\\end{figure}\n\n\\paragraph{Non-uniform inter-depth spacing.}\nFor Pythia nucleus, \\textsc{p90\\_ppl} drops from 483.7 (d0) to 61.4 (d1)---an 87\\% reduction---but only from 29.7 (d2) to 18.2 (d3), a 39\\% reduction.\nThis geometric compression of the feature space explains why adjacent-pair AUC decays monotonically (Figure~\\ref{fig:auc_decay}): each successive generation step yields diminishing statistical displacement.\n\n\\paragraph{Temperature-induced acceleration.}\nTemperature sampling ($\\tau{=}0.9$) applies uniform logit scaling rather than the hard truncation of nucleus or top-$k$, which accelerates convergence toward the low-entropy attractor described by \\citet{marchi2024_heat_death}.\nConcretely, feature values at depth $N$ under temperature sampling approximate those at depth $N{+}1$ under nucleus or top-$k$.\nThis shift yields higher in-distribution accuracy (Table~\\ref{tab:main_matrix}) because each depth occupies a more distinct region of feature space, but it also means the d1/d2 boundary under temperature is closer to the d2/d3 boundary under nucleus---a mismatch that creates reversal risk in cross-strategy transfer (\\S\\ref{sec:generalization}).\n\n\\paragraph{Three-tier strategy taxonomy.}\nThe trajectory data suggests a functional classification.\nNucleus sampling ($p{=}0.95$) serves as a stable baseline with moderate signal strength.\nTemperature sampling ($\\tau{=}0.9$) enhances the signal via accelerated convergence, yielding higher within-strategy accuracy but strategy-specific depth boundaries.\nTop-$k$ sampling ($k{=}50$) attenuates the signal---accuracy drops 6--9 points relative to nucleus---because hard truncation at a fixed vocabulary size preserves more of the original distribution's shape across depths, compressing inter-depth distances.\nNotably, top-$k$ preserves the \\emph{direction} of all feature trends despite the magnitude reduction, which has implications for ordinal classifiers that rely on monotonicity (\\S\\ref{sec:generalization}).",
      "numLines": 136,
      "startLine": 1,
      "totalLines": 136
    }
  },
  "sourceToolAssistantUUID": "b2e89ce1-63f1-4c6b-a623-9664945c6af3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-15T15:51:38.904Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NUaTd5kmS1ZDZQqkPKLbCq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dd047587-ac16-428d-a938-022f78c08208",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "e57693e2-1177-44f6-a9a5-00b724c555e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 31 · 2026-05-15T15:51:38.910Z_

<details><summary>↩ Tool result · `toolu_01NUaTd5kmS1ZDZQqkPKLbCq`</summary>

```text
1	\section{Generalization and Robustness}
2	\label{sec:generalization}
3	
4	We test whether the atlas results (69.6--85.4\%) reflect genuine statistical regularities or training artifacts, evaluating four axes: classifier choice (\S\ref{sec:gen:baselines}), cross-model transfer (\S\ref{sec:gen:crossmodel}), cross-strategy transfer (\S\ref{sec:gen:crossstrategy}), and end-to-end learning (\S\ref{sec:gen:dcol}).
5	
6	\subsection{Baseline Comparison}
7	\label{sec:gen:baselines}
8	
9	Table~\ref{tab:baselines} compares classification methods on the Pythia-1.4B nucleus setting.
10	Three feature-based methods---Random Forest (RF), CORAL ordinal regression \cite{coral2020}, and DivEye \cite{diveye2026}---all operate on the same 19 statistical features and achieve statistically indistinguishable accuracy (78.1--78.2\%; pairwise bootstrap $p>0.05$ after Bonferroni correction, 95\% CI within $\pm$1.1pp).
11	These three significantly outperform CE-MLP ($p<0.001$, $+$3.8pp), which in turn trails logistic regression by $\sim$0.1pp.
12	Single-feature regression on mean perplexity performs at chance (25.1\%), confirming that depth estimation requires the multi-dimensional feature representation defined in \S\ref{sec:method}.
13	
14	\begin{table}[t]
15	\centering
16	\small
17	\caption{Comparison of classification methods on Pythia-1.4B nucleus. RF, CORAL, and DivEye use the same 19 statistical features and are statistically indistinguishable (bootstrap $p>0.05$, Bonferroni-corrected). Chance = 25\%. 5-fold CV std: 0.2--0.9pp across all methods.}
18	\label{tab:baselines}
19	\begin{tabular}{lc}
20	\toprule
21	Method & 4-class Acc (\%) \\
22	\midrule
23	RF (19 features) & 78.2 \\
24	CORAL & 78.1 \\
25	DivEye & 78.2 \\
26	CE-MLP & 74.9 \\
27	LR & 75.0 \\
28	DeepSeek V3.2 (zero-shot)\footnotemark & 40.0 \\
29	ppl-regression (single feature) & 25.1 \\
30	\bottomrule
31	\end{tabular}
32	\footnotetext{Evaluated on 200 samples (approximately 50 per class) from the Pythia-1.4B nucleus cell only, due to API cost; 95\% CI: $\pm$6.8pp. All other methods use the full 20{,}000-sample set.}
33	\end{table}
34	
35	That three structurally different classifiers achieve identical performance confirms that the discriminative signal resides in the 19 features, not the classifier architecture; a zero-shot LLM baseline (DeepSeek V3.2) reaches only 40.0\%.
36	Figure~\ref{fig:confusion_matrix} shows d0 is near-perfectly identified in both settings; errors concentrate at the d2/d3 boundary in-distribution and spread across d1--d3 under cross-model transfer.
37	
38	\begin{figure}[t]
39	\centering
40	\includegraphics[width=\columnwidth]{../../figures/paper/fig_confusion_matrix.pdf}
41	\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\tau{=}0.9$, 85.4\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\%). d0 recall exceeds 99\% in both; errors spread across the d1--d3 range under transfer.}
42	\label{fig:confusion_matrix}
43	\end{figure}
44	
45	\subsection{Cross-Model Transfer}
46	\label{sec:gen:crossmodel}
47	
48	We perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\ref{tab:cross_model}).
49	
50	\begin{table}[t]
51	\centering
52	\small
53	\caption{Cross-model transfer (leave-one-out, nucleus only). Train on 2 model families, test on held-out 3rd. Chance = 25\%.}
54	\label{tab:cross_model}
55	\begin{tabular}{lccccc}
56	\toprule
57	Holdout & Acc & d0 & d1 & d2 & d3 \\
58	 & (\%) & Rec. & Rec. & Rec. & Rec. \\
59	\midrule
60	Pythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\
61	OLMo & \textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\
62	GPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\
63	\midrule
64	Mean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\
65	\bottomrule
66	\end{tabular}
67	\end{table}
68	
69	Mean transfer accuracy reaches 66.4\% (2.7$\times$ chance), though d0 recall ($>$98\%) inflates the headline; d2 recall drops to 26.8\% (Pythia holdout), making it the most confusable class.
70	
71	\subsection{Cross-Strategy Transfer}
72	\label{sec:gen:crossstrategy}
73	
74	We train on two decoding strategies and test on the held-out third (Table~\ref{tab:cross_strategy}).
75	
76	\begin{table}[t]
77	\centering
78	\small
79	\caption{Cross-strategy transfer (leave-one-out). Train on 2 strategies, test on held-out 3rd. Chance = 25\%.}
80	\label{tab:cross_strategy}
81	\begin{tabular}{lccc}
82	\toprule
83	Holdout & Pythia & OLMo & GPT-2 XL \\
84	 & Acc (\%) & Acc (\%) & Acc (\%) \\
85	\midrule
86	nucleus & \textbf{69.4} & \textbf{65.4} & \textbf{59.9} \\
87	temp ($\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\
88	top-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\
89	\bottomrule
90	\end{tabular}
91	\end{table}
92	
93	Mean cross-strategy accuracy (59.1\%) falls 7 points below cross-model transfer (66.4\%), indicating that strategy-induced distribution shifts pose a greater generalization challenge than architectural differences.
94	As with cross-model transfer, d0 recall remains high ($\geq$89.5\%) across all holdout settings, inflating the headline accuracy; d2 recall ranges from 3.7\% to 19\%, confirming mid-chain depths as the primary confusion locus across both transfer axes.
95	
96	\paragraph{Temperature-induced boundary inversion.}
97	Training on nucleus + top-$k$ and testing on temperature yields d1v2 AUC of 0.129 for GPT-2~XL and 0.253 for OLMo---both below 0.5, indicating that the d1/d2 decision boundary \emph{inverts} (Pythia retains a degraded 0.576), consistent with the accelerated convergence in \S\ref{sec:atlas:trajectories}.
98	Z-score normalization \cite{sugiyama2007_importance_weighting} improves logistic regression cross-strategy accuracy (25\%$\to$61\%) but does not recover the inversion---all three models worsen (GPT-2~XL 0.50$\to$0.24, OLMo 0.50$\to$0.19, Pythia 0.63$\to$0.52)---confirming a genuine geometry-level shift rather than a correctable scale difference.
99	
100	\subsection{End-to-End Learning}
101	\label{sec:gen:dcol}
102	
103	We finetune DeBERTa-v3-base and RoBERTa-base end-to-end (lr$\,{=}\,2{\times}10^{-5}$, 3 epochs, 5-fold CV) on Pythia-1.4B nucleus data.
104	Both converge to ${\sim}$59\% (RoBERTa 59.5$\pm$3.2\%, DeBERTa 58.3$\pm$4.7\%), 19pp below feature-based RF (78.2\%); the 1.2pp inter-backbone gap rules out architecture selection bias.
105	Both easily separate d0 (F1$>$0.95) but fail at adjacent-depth discrimination (d1/d2 F1$<$0.42).
106	Probing reveals a negative correlation between PLM attention and RF permutation importance for both backbones (DeBERTa $\rho{=}{-}0.484$, RoBERTa $\rho{=}{-}0.456$; zero top-5 overlap; Appendix~\ref{app:feature_overlap}), confirming that PLMs encode surface lexical cues while our features capture perplexity tail structure inaccessible to end-to-end learning.
107	
108	DCOL \cite{cloc2025}, which adds a contrastive ordinal loss, fared worse: across six iterations with two backbones (Appendix~\ref{app:dcol_iterations}), the best run (RoBERTa-large) reached only 64.5\% with severe overfitting, 13.7pp below RF.
109	That all end-to-end approaches---standard finetuning (58--60\%), DCOL (64.5\%)---substantially underperform feature-based methods (78.2\%) confirms that depth estimation requires explicit distributional statistics rather than learned text representations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e57693e2-1177-44f6-a9a5-00b724c555e2",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "6d229941-f256-4cf4-a43f-842249dddff1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
      "content": "\\section{Generalization and Robustness}\n\\label{sec:generalization}\n\nWe test whether the atlas results (69.6--85.4\\%) reflect genuine statistical regularities or training artifacts, evaluating four axes: classifier choice (\\S\\ref{sec:gen:baselines}), cross-model transfer (\\S\\ref{sec:gen:crossmodel}), cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}), and end-to-end learning (\\S\\ref{sec:gen:dcol}).\n\n\\subsection{Baseline Comparison}\n\\label{sec:gen:baselines}\n\nTable~\\ref{tab:baselines} compares classification methods on the Pythia-1.4B nucleus setting.\nThree feature-based methods---Random Forest (RF), CORAL ordinal regression \\cite{coral2020}, and DivEye \\cite{diveye2026}---all operate on the same 19 statistical features and achieve statistically indistinguishable accuracy (78.1--78.2\\%; pairwise bootstrap $p>0.05$ after Bonferroni correction, 95\\% CI within $\\pm$1.1pp).\nThese three significantly outperform CE-MLP ($p<0.001$, $+$3.8pp), which in turn trails logistic regression by $\\sim$0.1pp.\nSingle-feature regression on mean perplexity performs at chance (25.1\\%), confirming that depth estimation requires the multi-dimensional feature representation defined in \\S\\ref{sec:method}.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Comparison of classification methods on Pythia-1.4B nucleus. RF, CORAL, and DivEye use the same 19 statistical features and are statistically indistinguishable (bootstrap $p>0.05$, Bonferroni-corrected). Chance = 25\\%. 5-fold CV std: 0.2--0.9pp across all methods.}\n\\label{tab:baselines}\n\\begin{tabular}{lc}\n\\toprule\nMethod & 4-class Acc (\\%) \\\\\n\\midrule\nRF (19 features) & 78.2 \\\\\nCORAL & 78.1 \\\\\nDivEye & 78.2 \\\\\nCE-MLP & 74.9 \\\\\nLR & 75.0 \\\\\nDeepSeek V3.2 (zero-shot)\\footnotemark & 40.0 \\\\\nppl-regression (single feature) & 25.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\footnotetext{Evaluated on 200 samples (approximately 50 per class) from the Pythia-1.4B nucleus cell only, due to API cost; 95\\% CI: $\\pm$6.8pp. All other methods use the full 20{,}000-sample set.}\n\\end{table}\n\nThat three structurally different classifiers achieve identical performance confirms that the discriminative signal resides in the 19 features, not the classifier architecture; a zero-shot LLM baseline (DeepSeek V3.2) reaches only 40.0\\%.\nFigure~\\ref{fig:confusion_matrix} shows d0 is near-perfectly identified in both settings; errors concentrate at the d2/d3 boundary in-distribution and spread across d1--d3 under cross-model transfer.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{../../figures/paper/fig_confusion_matrix.pdf}\n\\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\\tau{=}0.9$, 85.4\\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\\%). d0 recall exceeds 99\\% in both; errors spread across the d1--d3 range under transfer.}\n\\label{fig:confusion_matrix}\n\\end{figure}\n\n\\subsection{Cross-Model Transfer}\n\\label{sec:gen:crossmodel}\n\nWe perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\\ref{tab:cross_model}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model transfer (leave-one-out, nucleus only). Train on 2 model families, test on held-out 3rd. Chance = 25\\%.}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nHoldout & Acc & d0 & d1 & d2 & d3 \\\\\n & (\\%) & Rec. & Rec. & Rec. & Rec. \\\\\n\\midrule\nPythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\\\\nOLMo & \\textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\\\\nGPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\\\\n\\midrule\nMean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean transfer accuracy reaches 66.4\\% (2.7$\\times$ chance), though d0 recall ($>$98\\%) inflates the headline; d2 recall drops to 26.8\\% (Pythia holdout), making it the most confusable class.\n\n\\subsection{Cross-Strategy Transfer}\n\\label{sec:gen:crossstrategy}\n\nWe train on two decoding strategies and test on the held-out third (Table~\\ref{tab:cross_strategy}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-strategy transfer (leave-one-out). Train on 2 strategies, test on held-out 3rd. Chance = 25\\%.}\n\\label{tab:cross_strategy}\n\\begin{tabular}{lccc}\n\\toprule\nHoldout & Pythia & OLMo & GPT-2 XL \\\\\n & Acc (\\%) & Acc (\\%) & Acc (\\%) \\\\\n\\midrule\nnucleus & \\textbf{69.4} & \\textbf{65.4} & \\textbf{59.9} \\\\\ntemp ($\\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\\\\ntop-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean cross-strategy accuracy (59.1\\%) falls 7 points below cross-model transfer (66.4\\%), indicating that strategy-induced distribution shifts pose a greater generalization challenge than architectural differences.\nAs with cross-model transfer, d0 recall remains high ($\\geq$89.5\\%) across all holdout settings, inflating the headline accuracy; d2 recall ranges from 3.7\\% to 19\\%, confirming mid-chain depths as the primary confusion locus across both transfer axes.\n\n\\paragraph{Temperature-induced boundary inversion.}\nTraining on nucleus + top-$k$ and testing on temperature yields d1v2 AUC of 0.129 for GPT-2~XL and 0.253 for OLMo---both below 0.5, indicating that the d1/d2 decision boundary \\emph{inverts} (Pythia retains a degraded 0.576), consistent with the accelerated convergence in \\S\\ref{sec:atlas:trajectories}.\nZ-score normalization \\cite{sugiyama2007_importance_weighting} improves logistic regression cross-strategy accuracy (25\\%$\\to$61\\%) but does not recover the inversion---all three models worsen (GPT-2~XL 0.50$\\to$0.24, OLMo 0.50$\\to$0.19, Pythia 0.63$\\to$0.52)---confirming a genuine geometry-level shift rather than a correctable scale difference.\n\n\\subsection{End-to-End Learning}\n\\label{sec:gen:dcol}\n\nWe finetune DeBERTa-v3-base and RoBERTa-base end-to-end (lr$\\,{=}\\,2{\\times}10^{-5}$, 3 epochs, 5-fold CV) on Pythia-1.4B nucleus data.\nBoth converge to ${\\sim}$59\\% (RoBERTa 59.5$\\pm$3.2\\%, DeBERTa 58.3$\\pm$4.7\\%), 19pp below feature-based RF (78.2\\%); the 1.2pp inter-backbone gap rules out architecture selection bias.\nBoth easily separate d0 (F1$>$0.95) but fail at adjacent-depth discrimination (d1/d2 F1$<$0.42).\nProbing reveals a negative correlation between PLM attention and RF permutation importance for both backbones (DeBERTa $\\rho{=}{-}0.484$, RoBERTa $\\rho{=}{-}0.456$; zero top-5 overlap; Appendix~\\ref{app:feature_overlap}), confirming that PLMs encode surface lexical cues while our features capture perplexity tail structure inaccessible to end-to-end learning.\n\nDCOL \\cite{cloc2025}, which adds a contrastive ordinal loss, fared worse: across six iterations with two backbones (Appendix~\\ref{app:dcol_iterations}), the best run (RoBERTa-large) reached only 64.5\\% with severe overfitting, 13.7pp below RF.\nThat all end-to-end approaches---standard finetuning (58--60\\%), DCOL (64.5\\%)---substantially underperform feature-based methods (78.2\\%) confirms that depth estimation requires explicit distributional statistics rather than learned text representations.",
      "numLines": 109,
      "startLine": 1,
      "totalLines": 109
    }
  },
  "sourceToolAssistantUUID": "e57693e2-1177-44f6-a9a5-00b724c555e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-15T15:51:39.377Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WLwm4stxGMzS8ktoUPLWzc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6d229941-f256-4cf4-a43f-842249dddff1",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "5fd1eb22-78a7-4c11-9d01-ede7c7e9e2c5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 33 · 2026-05-15T15:51:39.384Z_

<details><summary>↩ Tool result · `toolu_01WLwm4stxGMzS8ktoUPLWzc`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Depth-graduated data curation.}
5	Predicted depth can serve as a continuous quality proxy for importance weighting in curation pipelines \cite{dsir2023,qurating2024}, retaining shallow-generation text while down-weighting deeply recursive samples that binary filters \cite{drayson2025_detection_prevents_collapse} would indiscriminately discard.
6	
7	\paragraph{Deployment considerations.}
8	The temperature-induced d1/d2 AUC inversion (\S\ref{sec:gen:crossstrategy}) means deploying without knowing the target decoding strategy risks systematic prediction reversals; strategy-conditioned classifiers or automatic strategy identification are needed.
9	
10	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5fd1eb22-78a7-4c11-9d01-ede7c7e9e2c5",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "07352fe1-791b-449f-88a6-e97b9d70bd88",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Depth-graduated data curation.}\nPredicted depth can serve as a continuous quality proxy for importance weighting in curation pipelines \\cite{dsir2023,qurating2024}, retaining shallow-generation text while down-weighting deeply recursive samples that binary filters \\cite{drayson2025_detection_prevents_collapse} would indiscriminately discard.\n\n\\paragraph{Deployment considerations.}\nThe temperature-induced d1/d2 AUC inversion (\\S\\ref{sec:gen:crossstrategy}) means deploying without knowing the target decoding strategy risks systematic prediction reversals; strategy-conditioned classifiers or automatic strategy identification are needed.\n\n",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  },
  "sourceToolAssistantUUID": "5fd1eb22-78a7-4c11-9d01-ede7c7e9e2c5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-15T15:51:40.111Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PM5gUZtDPp1FtDroc7opWT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "07352fe1-791b-449f-88a6-e97b9d70bd88",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "eddd79b8-f28b-4d0b-ae68-24e9de5d5602",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 35 · 2026-05-15T15:51:40.128Z_

<details><summary>↩ Tool result · `toolu_01PM5gUZtDPp1FtDroc7opWT`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We introduced recursive generation depth estimation and showed that 19 lightweight statistical features---with p90 perplexity and surprisal variance as universal markers---achieve 70--85\% four-class accuracy (chance = 25\%) with $\mathrm{EDD}_{0.75}{=}4$.
5	Cross-model transfer reaches 66.4\% and cross-strategy 59.1\%, though the temperature-induced d1/d2 inversion and PLMs' ${\sim}$59\% ceiling underscore remaining challenges; future work should address wild-data transfer, larger scales, and strategy-conditioned classifiers.
6	Code and data will be released upon acceptance.
7	
8	\section*{Limitations}
9	\label{sec:limitations}
10	
11	\paragraph{Cross-strategy deployment constraint.}
12	Deploying depth estimators across decoding strategies requires knowing the target strategy type a priori.
13	Without this knowledge, d1/d2 predictions may systematically invert: cross-strategy holdout d1v2 AUC drops to 0.129 (GPT-2~XL) and 0.253 (OLMo) when temperature-sampled text is classified by a model trained on nucleus and top-$k$ (\S\ref{sec:gen:crossstrategy}).
14	Strategy-conditioned classifiers or automatic strategy identification are needed before deployment.
15	
16	\paragraph{d0 inflation of headline metrics.}
17	Depth~0 (human-written text) is near-perfectly separable (recall $>$98\% across all settings), inflating headline accuracy.
18	Cross-model transfer accuracy of 66.4\% is substantially driven by d0; d2 recall drops to 26.8\% in the worst case (Pythia holdout).
19	
20	\paragraph{Controlled vs.\ ecological setting.}
21	All experiments use Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models).
22	Transfer to mixed-domain corpora, instruction-tuned models, and larger scales (7B+) remains open.
23	Wild-data calibration is probed only indirectly; ecological transfer is future work.
24	
25	\paragraph{EDD threshold sensitivity.}
26	The Effective Discriminable Depth depends on the AUC threshold $T$: at $T{=}0.80$, several cells lose one discriminable depth level relative to $T{=}0.75$.
27	The choice of $T$ is application-dependent and affects reported EDD values.
28	
29	\paragraph{Reference model dependency.}
30	Surprisal-based features are computed relative to GPT-2 base (124M), introducing partial overlap when GPT-2~XL is held out, though GPT-2~XL holdout accuracy (67.6\%) does not exceed the unrelated OLMo (69.2\%).
31	The choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.
32	
33	\paragraph{Additional caveats.}
34	Detection features degrade under domain shift \cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.
35	\citet{bakshi2026_collapse_improvement} find that early recursion can temporarily \emph{improve} model quality, potentially violating the monotonicity assumption, and \citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "eddd79b8-f28b-4d0b-ae68-24e9de5d5602",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "50a9749a-f557-4f66-9262-24db677e1e6a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe introduced recursive generation depth estimation and showed that 19 lightweight statistical features---with p90 perplexity and surprisal variance as universal markers---achieve 70--85\\% four-class accuracy (chance = 25\\%) with $\\mathrm{EDD}_{0.75}{=}4$.\nCross-model transfer reaches 66.4\\% and cross-strategy 59.1\\%, though the temperature-induced d1/d2 inversion and PLMs' ${\\sim}$59\\% ceiling underscore remaining challenges; future work should address wild-data transfer, larger scales, and strategy-conditioned classifiers.\nCode and data will be released upon acceptance.\n\n\\section*{Limitations}\n\\label{sec:limitations}\n\n\\paragraph{Cross-strategy deployment constraint.}\nDeploying depth estimators across decoding strategies requires knowing the target strategy type a priori.\nWithout this knowledge, d1/d2 predictions may systematically invert: cross-strategy holdout d1v2 AUC drops to 0.129 (GPT-2~XL) and 0.253 (OLMo) when temperature-sampled text is classified by a model trained on nucleus and top-$k$ (\\S\\ref{sec:gen:crossstrategy}).\nStrategy-conditioned classifiers or automatic strategy identification are needed before deployment.\n\n\\paragraph{d0 inflation of headline metrics.}\nDepth~0 (human-written text) is near-perfectly separable (recall $>$98\\% across all settings), inflating headline accuracy.\nCross-model transfer accuracy of 66.4\\% is substantially driven by d0; d2 recall drops to 26.8\\% in the worst case (Pythia holdout).\n\n\\paragraph{Controlled vs.\\ ecological setting.}\nAll experiments use Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models).\nTransfer to mixed-domain corpora, instruction-tuned models, and larger scales (7B+) remains open.\nWild-data calibration is probed only indirectly; ecological transfer is future work.\n\n\\paragraph{EDD threshold sensitivity.}\nThe Effective Discriminable Depth depends on the AUC threshold $T$: at $T{=}0.80$, several cells lose one discriminable depth level relative to $T{=}0.75$.\nThe choice of $T$ is application-dependent and affects reported EDD values.\n\n\\paragraph{Reference model dependency.}\nSurprisal-based features are computed relative to GPT-2 base (124M), introducing partial overlap when GPT-2~XL is held out, though GPT-2~XL holdout accuracy (67.6\\%) does not exceed the unrelated OLMo (69.2\\%).\nThe choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.\n\n\\paragraph{Additional caveats.}\nDetection features degrade under domain shift \\cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.\n\\citet{bakshi2026_collapse_improvement} find that early recursion can temporarily \\emph{improve} model quality, potentially violating the monotonicity assumption, and \\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.",
      "numLines": 35,
      "startLine": 1,
      "totalLines": 35
    }
  },
  "sourceToolAssistantUUID": "eddd79b8-f28b-4d0b-ae68-24e9de5d5602",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-15T15:51:40.501Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CVzmM2uk8ioYHKE2kuHLUc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "50a9749a-f557-4f66-9262-24db677e1e6a",
  "isSidechain": false,
  "requestId": "req_011Cb4cz9uhZAXRytKKvoXMy",
  "type": "assistant",
  "uuid": "6f68218b-3d8b-44e4-b6fc-acbfab80aee9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XkRpD6BDVCTzQateR97Bvf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5938,
      "cache_read_input_tokens": 24110,
      "output_tokens": 1921,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5938,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1921,
          "cache_read_input_tokens": 24110,
          "cache_creation_input_tokens": 5938,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5938
          },
          "type": "message"
        }
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

_source line 37 · 2026-05-15T15:51:40.600Z_

```json
{
  "parentUuid": "efe18a27-23a5-4652-b0c5-c5d64b66e7d2",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "8c7748db-0d3b-471f-a43a-397d51b18ba2",
  "timestamp": "2026-05-15T15:51:40.600Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 38_

```json
{
  "type": "last-prompt",
  "leafUuid": "8c7748db-0d3b-471f-a43a-397d51b18ba2",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Runtime record

_source line 39_

```json
{
  "type": "ai-title",
  "aiTitle": "Expand bibliography and verify paper terminology consistency",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Assistant

_source line 40 · 2026-05-15T15:51:55.067Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the content. Let me analyze:

## Task 1: Bibliography count
Current bib has 38 entries. Already ≥ 25. All required references are present. Task 1 is satisfied.

## Task 2: Terminology consistency

Let me scan for terminology issues:

### "recursive generation depth" variants:
- abstract.tex: "recursive generation depth estimation" (line 3) ✓
- introduction.tex: "recursive generation depth estimation" (line 17) ✓
- method.tex: "recursive generation chain" (line 8), "recursive generation depth" (line 11) ✓


- atlas.tex: "recursive generation" (multiple) ✓
- conclusion.tex: "recursive generation depth estimation" (line 4) ✓

Now I need to check for problematic variants like "recursive depth" or "iteration depth" used inconsistently, and verify that "Depth Degradation Atlas" remains a proper name while checking if "quality degradation" appears elsewhere. I'm also tracking how "statistical features," "hand-crafted features," and "perplexity features" are used across the documents.

For "model collapse," the standard terminology is consistent throughout. The EDD acronym is properly defined in abstract.tex and referenced in method.tex and atlas.tex, so I should verify these definitions align. Let me search through the files to confirm all these patterns.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8c7748db-0d3b-471f-a43a-397d51b18ba2",
  "isSidechain": false,
  "requestId": "req_011Cb4d1z7ta94arMikFyvfK",
  "type": "assistant",
  "uuid": "33a5b835-5f1b-4b7c-8128-b6ad21a1abe0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L8ZMMBPrvwe4TQVYN3bTee",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17438,
      "cache_read_input_tokens": 30048,
      "output_tokens": 960,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17438,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 960,
          "cache_read_input_tokens": 30048,
          "cache_creation_input_tokens": 17438,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17438
          },
          "type": "message"
        }
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

_source line 41 · 2026-05-15T15:51:55.088Z_

All files read. Now scanning for terminology inconsistencies across the codebase.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "33a5b835-5f1b-4b7c-8128-b6ad21a1abe0",
  "isSidechain": false,
  "requestId": "req_011Cb4d1z7ta94arMikFyvfK",
  "type": "assistant",
  "uuid": "bbf9b1dc-94e7-4787-afaa-3961299256ee",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L8ZMMBPrvwe4TQVYN3bTee",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17438,
      "cache_read_input_tokens": 30048,
      "output_tokens": 960,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17438,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 960,
          "cache_read_input_tokens": 30048,
          "cache_creation_input_tokens": 17438,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17438
          },
          "type": "message"
        }
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

_source line 42 · 2026-05-15T15:51:56.492Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01WQo4e1DN3oVpshaV8gygvG`</summary>

```json
{
  "pattern": "recursive depth|iteration depth",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bbf9b1dc-94e7-4787-afaa-3961299256ee",
  "isSidechain": false,
  "requestId": "req_011Cb4d1z7ta94arMikFyvfK",
  "type": "assistant",
  "uuid": "41cd0fda-61da-40db-97bf-87e88a15eacf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L8ZMMBPrvwe4TQVYN3bTee",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17438,
      "cache_read_input_tokens": 30048,
      "output_tokens": 960,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17438,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 960,
          "cache_read_input_tokens": 30048,
          "cache_creation_input_tokens": 17438,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17438
          },
          "type": "message"
        }
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

_source line 43 · 2026-05-15T15:52:02.070Z_

<details><summary>↩ Tool result · `toolu_014KKk6MCjKJQhcrk68QSkS2`</summary>

```text
docs/paper/generalization.tex:10:Three feature-based methods---Random Forest (RF), CORAL ordinal regression \cite{coral2020}, and DivEye \cite{diveye2026}---all operate on the same 19 statistical features and achieve statistically indistinguishable accuracy (78.1--78.2\%; pairwise bootstrap $p>0.05$ after Bonferroni correction, 95\% CI within $\pm$1.1pp).
docs/paper/generalization.tex:98:Z-score normalization \cite{sugiyama2007_importance_weighting} improves logistic regression cross-strategy accuracy (25\%$\to$61\%) but does not recover the inversion---all three models worsen (GPT-2~XL 0.50$\to$0.24, OLMo 0.50$\to$0.19, Pythia 0.63$\to$0.52)---confirming a genuine geometry-level shift rather than a correctable scale difference.
docs/paper/generalization.tex:108:DCOL \cite{cloc2025}, which adds a contrastive ordinal loss, fared worse: across six iterations with two backbones (Appendix~\ref{app:dcol_iterations}), the best run (RoBERTa-large) reached only 64.5\% with severe overfitting, 13.7pp below RF.
docs/paper/introduction.tex:5:As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
docs/paper/introduction.tex:6:This model$\to$data$\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
docs/paper/introduction.tex:9:Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
docs/paper/introduction.tex:10:Watermarking \cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.
docs/paper/introduction.tex:11:The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
docs/paper/conclusion.tex:34:Detection features degrade under domain shift \cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.
docs/paper/discussion.tex:5:Predicted depth can serve as a continuous quality proxy for importance weighting in curation pipelines \cite{dsir2023,qurating2024}, retaining shallow-generation text while down-weighting deeply recursive samples that binary filters \cite{drayson2025_detection_prevents_collapse} would indiscriminately discard.
docs/paper/method.tex:24:Each model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \cite{holtzman2020_nucleus}, temperature sampling ($\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).
docs/paper/method.tex:32:Starting from a Wikipedia subset as seed text ($\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \cite{hu2022lora} with rank $r{=}16$, $\alpha{=}32$, learning rate $2{\times}10^{-4}$, batch size 8, for 3 epochs; (2)~generation of 5{,}000 passages (max 512 tokens) under the specified decoding strategy; (3)~the generated corpus becomes $\mathcal{D}_k$ and serves as training data for the next cycle.
docs/paper/method.tex:102:We compare against CORAL ordinal regression \cite{coral2020}, DivEye \cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \S\ref{sec:generalization}.
docs/paper/atlas.tex:53:These results align with theoretical predictions: recursive finetuning erodes the tail of the token-probability distribution \cite{shumailov2024_nature,dohmatob2024_tale_of_tails}, and high-percentile perplexity directly measures tail behavior.
docs/paper/related_work.tex:7:The MAD framework \cite{alemohammad2024_mad} extends this analysis to self-consuming generative models and quantifies the precision--recall tradeoff as synthetic data accumulates across generations.
docs/paper/related_work.tex:8:Mitigation strategies include retaining real data \cite{gerstgrasser2024_accumulate} and filtering synthetic samples via detection \cite{drayson2025_detection_prevents_collapse}.
docs/paper/related_work.tex:9:Recent work identifies non-monotonic dynamics \cite{bakshi2026_collapse_improvement}, fixed-point convergence \cite{marchi2024_heat_death}, contamination bounds \cite{wang2026_contamination}, curated pipelines \cite{falahati2026_curated}, knowledge collapse \cite{knowledge_collapse2025}, spectral signatures \cite{sigma2026_spectral}, and self-improving loops \cite{synthetic_eggs2026}.
docs/paper/related_work.tex:13:DetectGPT \cite{mitchell2023_detectgpt} introduced probability curvature---the tendency of model-generated text to occupy local maxima of the log-probability surface---as a zero-shot detection signal.
docs/paper/related_work.tex:15:Binoculars \cite{binoculars2024} exploits the perplexity ratio between two related models, achieving strong detection without training data.
docs/paper/related_work.tex:16:DivEye \cite{diveye2026} leverages surprisal diversity patterns, while GLTR \cite{gehrmann2019_gltr} provides statistical visualization of per-token likelihood ranks for human inspection.
docs/paper/related_work.tex:23:EditLens \cite{editlens2026} estimates the \emph{extent} of editing applied to a passage---a continuous measure of how much a text has been modified in a single pass---but does not model recursive generation chains.
docs/paper/related_work.tex:25:LOKI \cite{loki2025} provides a comprehensive benchmark spanning multiple synthetic data modalities but evaluates binary detection, not depth estimation.
docs/paper/related_work.tex:33:\citet{wiher2022_decoding} provide a systematic comparison of decoding methods on surface-level text properties, and Mirostat \cite{basu2021_mirostat} introduces perplexity-controlled decoding that actively regulates output entropy.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "932494d2-4811-424d-ac15-5f59584adfbd",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "761a914e-6b9a-422a-b60b-de9e7885a017",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/generalization.tex:10:Three feature-based methods---Random Forest (RF), CORAL ordinal regression \\cite{coral2020}, and DivEye \\cite{diveye2026}---all operate on the same 19 statistical features and achieve statistically indistinguishable accuracy (78.1--78.2\\%; pairwise bootstrap $p>0.05$ after Bonferroni correction, 95\\% CI within $\\pm$1.1pp).\ndocs/paper/generalization.tex:98:Z-score normalization \\cite{sugiyama2007_importance_weighting} improves logistic regression cross-strategy accuracy (25\\%$\\to$61\\%) but does not recover the inversion---all three models worsen (GPT-2~XL 0.50$\\to$0.24, OLMo 0.50$\\to$0.19, Pythia 0.63$\\to$0.52)---confirming a genuine geometry-level shift rather than a correctable scale difference.\ndocs/paper/generalization.tex:108:DCOL \\cite{cloc2025}, which adds a contrastive ordinal loss, fared worse: across six iterations with two backbones (Appendix~\\ref{app:dcol_iterations}), the best run (RoBERTa-large) reached only 64.5\\% with severe overfitting, 13.7pp below RF.\ndocs/paper/introduction.tex:5:As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\ndocs/paper/introduction.tex:6:This model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\ndocs/paper/introduction.tex:9:Binary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\ndocs/paper/introduction.tex:10:Watermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\ndocs/paper/introduction.tex:11:The model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\ndocs/paper/conclusion.tex:34:Detection features degrade under domain shift \\cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.\ndocs/paper/discussion.tex:5:Predicted depth can serve as a continuous quality proxy for importance weighting in curation pipelines \\cite{dsir2023,qurating2024}, retaining shallow-generation text while down-weighting deeply recursive samples that binary filters \\cite{drayson2025_detection_prevents_collapse} would indiscriminately discard.\ndocs/paper/method.tex:24:Each model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\ndocs/paper/method.tex:32:Starting from a Wikipedia subset as seed text ($\\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \\cite{hu2022lora} with rank $r{=}16$, $\\alpha{=}32$, learning rate $2{\\times}10^{-4}$, batch size 8, for 3 epochs; (2)~generation of 5{,}000 passages (max 512 tokens) under the specified decoding strategy; (3)~the generated corpus becomes $\\mathcal{D}_k$ and serves as training data for the next cycle.\ndocs/paper/method.tex:102:We compare against CORAL ordinal regression \\cite{coral2020}, DivEye \\cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \\S\\ref{sec:generalization}.\ndocs/paper/atlas.tex:53:These results align with theoretical predictions: recursive finetuning erodes the tail of the token-probability distribution \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails}, and high-percentile perplexity directly measures tail behavior.\ndocs/paper/related_work.tex:7:The MAD framework \\cite{alemohammad2024_mad} extends this analysis to self-consuming generative models and quantifies the precision--recall tradeoff as synthetic data accumulates across generations.\ndocs/paper/related_work.tex:8:Mitigation strategies include retaining real data \\cite{gerstgrasser2024_accumulate} and filtering synthetic samples via detection \\cite{drayson2025_detection_prevents_collapse}.\ndocs/paper/related_work.tex:9:Recent work identifies non-monotonic dynamics \\cite{bakshi2026_collapse_improvement}, fixed-point convergence \\cite{marchi2024_heat_death}, contamination bounds \\cite{wang2026_contamination}, curated pipelines \\cite{falahati2026_curated}, knowledge collapse \\cite{knowledge_collapse2025}, spectral signatures \\cite{sigma2026_spectral}, and self-improving loops \\cite{synthetic_eggs2026}.\ndocs/paper/related_work.tex:13:DetectGPT \\cite{mitchell2023_detectgpt} introduced probability curvature---the tendency of model-generated text to occupy local maxima of the log-probability surface---as a zero-shot detection signal.\ndocs/paper/related_work.tex:15:Binoculars \\cite{binoculars2024} exploits the perplexity ratio between two related models, achieving strong detection without training data.\ndocs/paper/related_work.tex:16:DivEye \\cite{diveye2026} leverages surprisal diversity patterns, while GLTR \\cite{gehrmann2019_gltr} provides statistical visualization of per-token likelihood ranks for human inspection.\ndocs/paper/related_work.tex:23:EditLens \\cite{editlens2026} estimates the \\emph{extent} of editing applied to a passage---a continuous measure of how much a text has been modified in a single pass---but does not model recursive generation chains.\ndocs/paper/related_work.tex:25:LOKI \\cite{loki2025} provides a comprehensive benchmark spanning multiple synthetic data modalities but evaluates binary detection, not depth estimation.\ndocs/paper/related_work.tex:33:\\citet{wiher2022_decoding} provide a systematic comparison of decoding methods on surface-level text properties, and Mirostat \\cite{basu2021_mirostat} introduces perplexity-controlled decoding that actively regulates output entropy.",
    "numLines": 23
  },
  "sourceToolAssistantUUID": "932494d2-4811-424d-ac15-5f59584adfbd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-15T15:51:56.536Z_

<details><summary>↩ Tool result · `toolu_01WQo4e1DN3oVpshaV8gygvG`</summary>

```text
docs/paper/introduction.tex:12:No existing method estimates the ordinal recursive depth of a text passage from its content alone.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "41cd0fda-61da-40db-97bf-87e88a15eacf",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "30b48db9-5fae-483e-b326-5ab88ffdcd92",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/introduction.tex:12:No existing method estimates the ordinal recursive depth of a text passage from its content alone.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "41cd0fda-61da-40db-97bf-87e88a15eacf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-15T15:52:00.525Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01R8WmZt5ENYPizLqR6gcd82`</summary>

```json
{
  "pattern": "quality degradation|hand-crafted|perplexity features",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "30b48db9-5fae-483e-b326-5ab88ffdcd92",
  "isSidechain": false,
  "requestId": "req_011Cb4d1z7ta94arMikFyvfK",
  "type": "assistant",
  "uuid": "82aab320-b846-48ff-970d-8f935a9bffbc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L8ZMMBPrvwe4TQVYN3bTee",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17438,
      "cache_read_input_tokens": 30048,
      "output_tokens": 960,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17438,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 960,
          "cache_read_input_tokens": 30048,
          "cache_creation_input_tokens": 17438,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17438
          },
          "type": "message"
        }
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

_source line 46 · 2026-05-15T15:52:00.558Z_

<details><summary>↩ Tool result · `toolu_01R8WmZt5ENYPizLqR6gcd82`</summary>

```text
docs/paper/method.tex:75:While correlated with perplexity features, surprisal variance captures second-order structure---the variability of token predictability---that is not redundant with perplexity moments.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "82aab320-b846-48ff-970d-8f935a9bffbc",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "4558028a-a314-46f5-ab28-1d038e73d3a4",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/method.tex:75:While correlated with perplexity features, surprisal variance captures second-order structure---the variability of token predictability---that is not redundant with perplexity moments.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "82aab320-b846-48ff-970d-8f935a9bffbc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-15T15:52:01.563Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01SpHSiUaew24Kn2zkMuUtNj`</summary>

```json
{
  "pattern": "recursive collapse",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4558028a-a314-46f5-ab28-1d038e73d3a4",
  "isSidechain": false,
  "requestId": "req_011Cb4d1z7ta94arMikFyvfK",
  "type": "assistant",
  "uuid": "58625d4f-5d24-4654-a6b5-3be01294f65c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L8ZMMBPrvwe4TQVYN3bTee",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17438,
      "cache_read_input_tokens": 30048,
      "output_tokens": 960,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17438,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 960,
          "cache_read_input_tokens": 30048,
          "cache_creation_input_tokens": 17438,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17438
          },
          "type": "message"
        }
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

_source line 48 · 2026-05-15T15:52:01.597Z_

<details><summary>↩ Tool result · `toolu_01SpHSiUaew24Kn2zkMuUtNj`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "58625d4f-5d24-4654-a6b5-3be01294f65c",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "f38873ac-9321-431b-a473-1556068bffdd",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "58625d4f-5d24-4654-a6b5-3be01294f65c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-15T15:52:02.042Z_

<details open><summary>🔧 Tool call — Grep · `toolu_014KKk6MCjKJQhcrk68QSkS2`</summary>

```json
{
  "pattern": "\\\\cite\\{",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f38873ac-9321-431b-a473-1556068bffdd",
  "isSidechain": false,
  "requestId": "req_011Cb4d1z7ta94arMikFyvfK",
  "type": "assistant",
  "uuid": "932494d2-4811-424d-ac15-5f59584adfbd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L8ZMMBPrvwe4TQVYN3bTee",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17438,
      "cache_read_input_tokens": 30048,
      "output_tokens": 960,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17438,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 960,
          "cache_read_input_tokens": 30048,
          "cache_creation_input_tokens": 17438,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17438
          },
          "type": "message"
        }
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

_source line 50 · 2026-05-15T15:52:38.093Z_

<details><summary>Logged reasoning block</summary>

```text
Let me analyze the findings:

### Terminology issues found:

1. **"recursive depth"** - Found in introduction.tex line 12: "ordinal recursive depth" — this is fine in context ("ordinal recursive depth of a text passage"), not a variant that needs changing.

2. **"perplexity features"** - Found in method.tex line 75: "correlated with perplexity features" — this should be "statistical features" for consistency, or more precisely it's referring to the perplexity statistics specifically. Actually, re-reading the context: "While correlated with perplexity features, surprisal variance captures..." — here "perplexity features" specifically refers to the perplexity statistics sub-category, which is appropriate since the sentence is distinguishing surprisal from perplexity. 

The paper defines a "Perplexity statistics" category in the features table, so using "perplexity features" to refer to that specific sub-group is acceptable.

3. **No "quality degradation"** found — good, "depth degradation" is used consistently for the Atlas name.

4. **No "recursive collapse"** — "model collapse" used consistently throughout. Good.

5. **No "hand-crafted features"** — good.

Now let me check EDD definition locations:
- Abstract line 6: "Effective Discriminable Depth (EDD)" ✓ defined
- Method section 4.4 (sec:method: edd): "Effective Discriminable Depth (EDD)" ✓ defined  
- Atlas section: references EDD ✓

Checking "generation depth" vs "recursive generation depth" more carefully. The abstract and introduction both use the full form "recursive generation depth estimation" on first occurrence, which is correct. The method section shortens it to "recursive generation depth," which is fine. However, I notice introduction line 12 uses "ordinal recursive depth" — that should be "recursive generation depth" for consistency. Let me fix that.

Now moving to orphan bibliography cleanup. I'm extracting all bibliography keys and cross-referencing them against what's actually cited in the paper.

Compiling the full list of references from the bib file... I'm continuing through the citation list, verifying each reference against what appears in the actual LaTeX files. Most of these are checking out, though I notice falahati2026_curated at the end seems to be cut off—I should verify whether that one is actually cited or if there's more to check.

Now I'm also realizing I need to be more thorough about searching for \citet{} commands in addition to \cite{}, since those are different citation styles. Looking through the tex files, I'm finding several instances where \citet{} is used instead, like with drayson2025, fast_detectgpt2024, and dohmatob2024, so I need to make sure I'm catching both citation formats.

Continuing through the rest of the \citet{} citations I found in the files... I'm continuing through the bibliography to verify all citations are accounted for—checking off the remaining entries from Mohamed through Finlayson, and it looks like everything has been cited somewhere in the document. Finishing the verification of the remaining entries and confirming all 38 references are properly cited in the document. Now I should do a more comprehensive search to make sure I haven't missed any citations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "761a914e-6b9a-422a-b60b-de9e7885a017",
  "isSidechain": false,
  "requestId": "req_011Cb4d3aJUaAZhhUaUDJhTd",
  "type": "assistant",
  "uuid": "307a048f-0dcb-4d59-b419-35e651708076",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015zaif5DBti9YHJrYkzLmE9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2963,
      "cache_read_input_tokens": 47486,
      "output_tokens": 2645,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2963,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2645,
          "cache_read_input_tokens": 47486,
          "cache_creation_input_tokens": 2963,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2963
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-15T15:52:38.103Z_

Let me also check for `\citet` citations to get the full picture.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "307a048f-0dcb-4d59-b419-35e651708076",
  "isSidechain": false,
  "requestId": "req_011Cb4d3aJUaAZhhUaUDJhTd",
  "type": "assistant",
  "uuid": "af6118f5-ba43-49a8-b15e-7a7300c329c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015zaif5DBti9YHJrYkzLmE9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2963,
      "cache_read_input_tokens": 47486,
      "output_tokens": 2645,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2963,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2645,
          "cache_read_input_tokens": 47486,
          "cache_creation_input_tokens": 2963,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2963
          },
          "type": "message"
        }
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

_source line 52 · 2026-05-15T15:52:38.146Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Kp1a8dom2wfDZNkvdosyzQ`</summary>

```json
{
  "pattern": "\\\\citet\\{",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "af6118f5-ba43-49a8-b15e-7a7300c329c2",
  "isSidechain": false,
  "requestId": "req_011Cb4d3aJUaAZhhUaUDJhTd",
  "type": "assistant",
  "uuid": "1a6e3a7f-ac7d-47cc-a3ed-65125bd73e46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015zaif5DBti9YHJrYkzLmE9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2963,
      "cache_read_input_tokens": 47486,
      "output_tokens": 2645,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2963,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2645,
          "cache_read_input_tokens": 47486,
          "cache_creation_input_tokens": 2963,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2963
          },
          "type": "message"
        }
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

_source line 53 · 2026-05-15T15:52:38.175Z_

<details><summary>↩ Tool result · `toolu_01Kp1a8dom2wfDZNkvdosyzQ`</summary>

```text
docs/paper/introduction.tex:11:The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
docs/paper/method.tex:35:We adopt standard LoRA hyperparameters ($r{=}16$, $\alpha{=}32$, dropout$\,{=}\,0.05$) following \citet{hu2022lora}, applied uniformly across all models.
docs/paper/conclusion.tex:35:\citet{bakshi2026_collapse_improvement} find that early recursion can temporarily \emph{improve} model quality, potentially violating the monotonicity assumption, and \citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.
docs/paper/atlas.tex:127:Temperature sampling ($\tau{=}0.9$) applies uniform logit scaling rather than the hard truncation of nucleus or top-$k$, which accelerates convergence toward the low-entropy attractor described by \citet{marchi2024_heat_death}.
docs/paper/related_work.tex:5:\citet{shumailov2024_nature} demonstrate that recursively training language models on their own outputs erodes distributional tails, eventually collapsing the output distribution to a narrow mode.
docs/paper/related_work.tex:6:\citet{dohmatob2024_tale_of_tails} formalize this phenomenon through scaling laws that distinguish tail \emph{narrowing} (reduced variance) from tail \emph{cutting} (lost support), showing both accelerate with generation depth; \citet{dohmatob2024_strong_collapse} establish strong collapse guarantees, and \citet{dohmatob2024_demystified} analyze the regression case.
docs/paper/related_work.tex:14:\citet{fast_detectgpt2024} improve computational efficiency by replacing random perturbations with conditional probability curvature from a surrogate model.
docs/paper/related_work.tex:17:\citet{sadasivan2023_paraphrase} expose fundamental limits: paraphrasing attacks reduce detection accuracy to near chance, and \citet{pudasaini2026_detection_fails} show detection degrades under distribution shift between training and deployment domains.
docs/paper/related_work.tex:18:\citet{pu2026_generator_barrier} formalize a generator barrier bounding detection performance when the generator is unknown.
docs/paper/related_work.tex:24:\citet{uchendu2020_attribution} formulate authorship attribution as multi-source classification, identifying \emph{which} model generated a text rather than \emph{how many} recursive steps it has undergone.
docs/paper/related_work.tex:26:\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, quantifying information distortion across rounds; while their work measures forward degradation fidelity, our task performs the inverse: classifying generation depth from text alone, without access to the generation chain.
docs/paper/related_work.tex:30:\citet{holtzman2020_nucleus} show that unrestricted sampling produces degenerate repetitions and propose nucleus sampling to maintain output diversity.
docs/paper/related_work.tex:31:\citet{finlayson2024_closing} demonstrate that decoding parameters affect downstream evaluation metrics in non-trivial ways.
docs/paper/related_work.tex:32:\citet{garces_arias2025_decoding_decoded} find that the effect of decoding strategies on text quality is model-dependent, complicating universal quality claims.
docs/paper/related_work.tex:33:\citet{wiher2022_decoding} provide a systematic comparison of decoding methods on surface-level text properties, and Mirostat \cite{basu2021_mirostat} introduces perplexity-controlled decoding that actively regulates output entropy.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1a6e3a7f-ac7d-47cc-a3ed-65125bd73e46",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "3a0a850d-5ef2-47cb-a8a0-28b22d0c5a3f",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/introduction.tex:11:The model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\ndocs/paper/method.tex:35:We adopt standard LoRA hyperparameters ($r{=}16$, $\\alpha{=}32$, dropout$\\,{=}\\,0.05$) following \\citet{hu2022lora}, applied uniformly across all models.\ndocs/paper/conclusion.tex:35:\\citet{bakshi2026_collapse_improvement} find that early recursion can temporarily \\emph{improve} model quality, potentially violating the monotonicity assumption, and \\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.\ndocs/paper/atlas.tex:127:Temperature sampling ($\\tau{=}0.9$) applies uniform logit scaling rather than the hard truncation of nucleus or top-$k$, which accelerates convergence toward the low-entropy attractor described by \\citet{marchi2024_heat_death}.\ndocs/paper/related_work.tex:5:\\citet{shumailov2024_nature} demonstrate that recursively training language models on their own outputs erodes distributional tails, eventually collapsing the output distribution to a narrow mode.\ndocs/paper/related_work.tex:6:\\citet{dohmatob2024_tale_of_tails} formalize this phenomenon through scaling laws that distinguish tail \\emph{narrowing} (reduced variance) from tail \\emph{cutting} (lost support), showing both accelerate with generation depth; \\citet{dohmatob2024_strong_collapse} establish strong collapse guarantees, and \\citet{dohmatob2024_demystified} analyze the regression case.\ndocs/paper/related_work.tex:14:\\citet{fast_detectgpt2024} improve computational efficiency by replacing random perturbations with conditional probability curvature from a surrogate model.\ndocs/paper/related_work.tex:17:\\citet{sadasivan2023_paraphrase} expose fundamental limits: paraphrasing attacks reduce detection accuracy to near chance, and \\citet{pudasaini2026_detection_fails} show detection degrades under distribution shift between training and deployment domains.\ndocs/paper/related_work.tex:18:\\citet{pu2026_generator_barrier} formalize a generator barrier bounding detection performance when the generator is unknown.\ndocs/paper/related_work.tex:24:\\citet{uchendu2020_attribution} formulate authorship attribution as multi-source classification, identifying \\emph{which} model generated a text rather than \\emph{how many} recursive steps it has undergone.\ndocs/paper/related_work.tex:26:\\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, quantifying information distortion across rounds; while their work measures forward degradation fidelity, our task performs the inverse: classifying generation depth from text alone, without access to the generation chain.\ndocs/paper/related_work.tex:30:\\citet{holtzman2020_nucleus} show that unrestricted sampling produces degenerate repetitions and propose nucleus sampling to maintain output diversity.\ndocs/paper/related_work.tex:31:\\citet{finlayson2024_closing} demonstrate that decoding parameters affect downstream evaluation metrics in non-trivial ways.\ndocs/paper/related_work.tex:32:\\citet{garces_arias2025_decoding_decoded} find that the effect of decoding strategies on text quality is model-dependent, complicating universal quality claims.\ndocs/paper/related_work.tex:33:\\citet{wiher2022_decoding} provide a systematic comparison of decoding methods on surface-level text properties, and Mirostat \\cite{basu2021_mirostat} introduces perplexity-controlled decoding that actively regulates output entropy.",
    "numLines": 15
  },
  "sourceToolAssistantUUID": "1a6e3a7f-ac7d-47cc-a3ed-65125bd73e46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 54_

```json
{
  "type": "last-prompt",
  "leafUuid": "3a0a850d-5ef2-47cb-a8a0-28b22d0c5a3f",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Runtime record

_source line 55_

```json
{
  "type": "ai-title",
  "aiTitle": "Expand bibliography and verify paper terminology consistency",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Assistant

_source line 56 · 2026-05-15T15:52:48.328Z_

<details><summary>Logged reasoning block</summary>

```text
Good. Now I have a complete picture. Let me compile the results:

## Task 1: Bibliography
38 entries, all required references present. ≥ 25 ✓. No additions needed.

## Task 2: Terminology consistency

Only one issue found:
- introduction.tex line 12: "ordinal recursive depth" should be "ordinal recursive generation depth" for consistency

Everything else is consistent:
- "recursive generation depth" is used as the full form, "generation depth" as shorthand — fine
- "Depth Degradation Atlas" used consistently as proper name


- "model collapse" used consistently throughout
- "statistical features" is the standard term; "perplexity features" in method.tex line 75 is contextually appropriate as it refers to the perplexity statistics sub-group
- EDD is properly defined at first occurrence in the abstract, then formally re-introduced in method.tex section 4.4 without redundancy

I need to fix one terminology issue in introduction.tex line 12, then verify the bibliography—all 38 entries are cited, so there's nothing to clean up there.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3a0a850d-5ef2-47cb-a8a0-28b22d0c5a3f",
  "isSidechain": false,
  "requestId": "req_011Cb4d6EUhVhcw1Yas5UjEM",
  "type": "assistant",
  "uuid": "4f2de2ba-cc9f-430b-8f65-e6cf956e73d0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0193nqtw9xAX35cgaphMPtvq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3617,
      "cache_read_input_tokens": 50449,
      "output_tokens": 638,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3617,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 638,
          "cache_read_input_tokens": 50449,
          "cache_creation_input_tokens": 3617,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3617
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-15T15:52:49.338Z_

Analysis complete. Here are the findings:

**Task 1 (Bibliography):** 38 entries already present. All required references accounted for. Already ≥ 25.

**Task 2 (Terminology):** One inconsistency found — introduction.tex line 12 uses "ordinal recursive depth" instead of "ordinal recursive generation depth". Fixing now.

**Task 3 (Orphan bib):** All 38 bib keys are cited in at least one .tex file. No orphans.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4f2de2ba-cc9f-430b-8f65-e6cf956e73d0",
  "isSidechain": false,
  "requestId": "req_011Cb4d6EUhVhcw1Yas5UjEM",
  "type": "assistant",
  "uuid": "895a869b-6100-45de-a0eb-ee17666f1ee2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0193nqtw9xAX35cgaphMPtvq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3617,
      "cache_read_input_tokens": 50449,
      "output_tokens": 638,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3617,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 638,
          "cache_read_input_tokens": 50449,
          "cache_creation_input_tokens": 3617,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3617
          },
          "type": "message"
        }
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

_source line 58 · 2026-05-15T15:52:50.368Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01YMGc47LPfgt8PTuBKGYSEh`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
  "old_string": "No existing method estimates the ordinal recursive depth of a text passage from its content alone.",
  "new_string": "No existing method estimates the ordinal recursive generation depth of a text passage from its content alone."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "895a869b-6100-45de-a0eb-ee17666f1ee2",
  "isSidechain": false,
  "requestId": "req_011Cb4d6EUhVhcw1Yas5UjEM",
  "type": "assistant",
  "uuid": "68339d42-e036-4252-8585-da0c36f72fc7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0193nqtw9xAX35cgaphMPtvq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3617,
      "cache_read_input_tokens": 50449,
      "output_tokens": 638,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3617,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 638,
          "cache_read_input_tokens": 50449,
          "cache_creation_input_tokens": 3617,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3617
          },
          "type": "message"
        }
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

_source line 59 · 2026-05-15T15:52:50.390Z_

<details><summary>↩ Tool result · `toolu_01YMGc47LPfgt8PTuBKGYSEh`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "68339d42-e036-4252-8585-da0c36f72fc7",
  "isSidechain": false,
  "promptId": "47a981b5-fed0-4f5d-83ff-bac343cb3a30",
  "type": "user",
  "uuid": "907e9b6e-46d7-47d8-aac9-f45c46f7c87a",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
    "oldString": "No existing method estimates the ordinal recursive depth of a text passage from its content alone.",
    "newString": "No existing method estimates the ordinal recursive generation depth of a text passage from its content alone.",
    "originalFile": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive depth of a text passage from its content alone.\n\nOur key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints exhibit universal stability across model families and decoding strategies.\nSpecifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 7/9 model--strategy configurations, respectively.\n\nWe formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.\nGiven a text passage, we compute a 19-dimensional feature vector from reference-model perplexity statistics---capturing distributional location, spread, tail behavior, and lexical diversity---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).\nTo systematically characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.\nThe atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\n\\begin{itemize}\n    \\item \\textbf{Task formalization.} We define recursive generation depth estimation as ordinal classification and introduce the EDD metric, which summarizes the maximum depth at which adjacent generations remain separable above a given AUC threshold.\n\n    \\item \\textbf{Depth Degradation Atlas.} We construct a systematic $3 \\times 3$ map across model families and decoding strategies, revealing that \\textsc{p90\\_ppl} ranks in the top 2 in all 9 cells (100\\%) and \\textsc{var\\_surprisal} in 7/9 (78\\%), with a mean Spearman rank correlation of $\\rho{=}0.868$ across importance vectors. The extended Pythia nucleus pipeline (d0--d5) yields $\\mathrm{EDD}_{0.75}{=}4$, establishing that depth discrimination persists through four recursive steps before falling below threshold.\n\n    \\item \\textbf{Generalization analysis.} Cross-model leave-one-out transfer achieves 66.4\\% and cross-strategy transfer 59.1\\% (chance = 25\\%). We identify a temperature-induced d1/d2 AUC inversion (GPT-2~XL: 0.129, OLMo: 0.253) that z-score normalization cannot resolve, confirming a geometry-level shift.\n\n    \\item \\textbf{End-to-end learning as negative result.} Both DeBERTa-v3-base (58.3\\%) and RoBERTa-base (59.5\\%) achieve ${\\sim}$59\\% via end-to-end finetuning---19pp below feature-based classifiers (78.2\\%)---with the architecture-invariant gap ruling out model selection bias. Probing reveals significant negative correlations (DeBERTa: $\\rho{=}{-}0.48$, RoBERTa: $\\rho{=}{-}0.46$) between transformer attention and RF feature importance, confirming complementary representations.\n\\end{itemize}",
    "structuredPatch": [
      {
        "oldStart": 9,
        "oldLines": 7,
        "newStart": 9,
        "newLines": 7,
        "lines": [
          " Binary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.",
          " Watermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.",
          " The model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.",
          "-No existing method estimates the ordinal recursive depth of a text passage from its content alone.",
          "+No existing method estimates the ordinal recursive generation depth of a text passage from its content alone.",
          " ",
          " Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints exhibit universal stability across model families and decoding strategies.",
          " Specifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 7/9 model--strategy configurations, respectively."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "68339d42-e036-4252-8585-da0c36f72fc7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 60 · 2026-05-15T15:53:05.296Z_

## 结果

### Task 1: Bibliography — 已满足
38 条 bib 条目，≥ 25。任务要求的所有引用均已存在：Kirchenbauer, Alemohammad, Dohmatob (tale of tails + strong + demystified), Gerstgrasser, Shumailov, DSIR, QuRating, Uchendu, Binoculars, Fast-DetectGPT, DivEye, Garces Arias, Holtzman, Sadasivan, CORAL, CLOC, Drayson, EditLens, Bakshi, Marchi, Pudasaini, Falahati, Sugiyama, Hu (LoRA)。无需新增。

### Task 2: 术语一致性 — 1 处修正
- `introduction.tex:12` "ordinal recursive depth" → "ordinal recursive generation depth"
- 其余术语一致：首次出现均用 "recursive generation depth"，后续缩写 "generation depth"；"model collapse" 统一使用文献标准用法；"statistical features" 全文一致；EDD 在 abstract 首次出现时已定义。

### Task 3: Orphan bib — 无 orphan
38/38 条 bib 条目均在 .tex 文件中被引用，无需标记。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "907e9b6e-46d7-47d8-aac9-f45c46f7c87a",
  "isSidechain": false,
  "requestId": "req_011Cb4d78ezG8a9a7ihr7wgW",
  "type": "assistant",
  "uuid": "ef6b29f8-da6a-4c2d-8cfd-1652cca6bb2f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NjApk2qbKa7TZ9mHRWEN8F",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 711,
      "cache_read_input_tokens": 54066,
      "output_tokens": 357,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 711,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 357,
          "cache_read_input_tokens": 54066,
          "cache_creation_input_tokens": 711,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 711
          },
          "type": "message"
        }
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

_source line 61_

```json
{
  "type": "last-prompt",
  "leafUuid": "ef6b29f8-da6a-4c2d-8cfd-1652cca6bb2f",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

### Runtime record

_source line 62_

```json
{
  "type": "ai-title",
  "aiTitle": "Expand bibliography and verify paper terminology consistency",
  "sessionId": "26d975ec-e008-4c6a-b9fc-a4b9bbf1910e"
}
```

---

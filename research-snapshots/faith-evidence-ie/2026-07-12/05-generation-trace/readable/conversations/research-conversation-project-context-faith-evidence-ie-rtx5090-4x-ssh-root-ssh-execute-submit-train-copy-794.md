# Research conversation: <project_context> # 项目: faith-evidence-ie ## 运行环境 - 服务器名: rtx5090-4x - SSH 账户: root（调用 ssh_execute / submit_training_job

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 78
- **Recorded user turns:** 1
- **Tool calls:** 21
- **Original source:** `logs/chats/exported-trajectories/account-2/7c9d941b-0177-4185-b3c0-aef43b48d2e1.jsonl`
- **Structured JSON:** [`7e1f8bd5a6fe936107b7.json`](../../sessions/7e/7e1f8bd5a6fe936107b7.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-21T02:45:27.308Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-21T02:45:27.308Z",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "content": "&lt;project_context>\n# 项目: faith-evidence-ie\n\n## 运行环境\n- 服务器名: rtx5090-4x\n- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account=\"root\"）\n- SSH 连接命令: ssh rtx5090-4x  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/autodl-tmp/freige\n\n## ⚠️ 活跃约束（必须遵守）\n\n- **C001**: 提交 eval 前必须 nvidia-smi 确认目标 GPU 显存占用 < 2GB，否则不提交、换卡或等待（原因：本 session 已 5 次因 eval 提交到被占用 GPU 导致 OOM，修复 eval 也因此作废。eval 推理需要接近全部显存，与训练共享必然 OOM。） [来自 D064]\n- **C002**: 提交训练/评估任务时必须在命令前设置 CUDA_VISIBLE_DEVICES=X，禁止依赖 device_map=\"auto\" 自动分配 GPU（原因：plan_011 和 rsft_ced_s45_train_r3 两次因未设 CUDA_VISIBLE_DEVICES 导致 device_map=\"auto\" 跨 GPU 分布，造成 OOM 和资源冲突。已知 bug 重复发生。）\n- **C003**: 提交训练任务时必须在命令前设置 CUDA_VISIBLE_DEVICES=X，禁止依赖 device_map=\"auto\" 自动分配 GPU（原因：plan_011 和 rsft_ced_s45_train_r3 均因未设 CUDA_VISIBLE_DEVICES 导致模型跨 GPU 分布，造成 OOM 或显存冲突。已重复发生两次。）\n- **C004**: Registry 标记 killed 时必须同时 kill -9 PID 并 ps 验证进程已终止，否则 killed 状态不可信（原因：rsft_ced_s45_train_r2 (PID 276148) registry 标记 killed 但进程未实际终止，占用 cuda:2 31.6GB 导致 r3 OOM。plan_011 也有类似模式。Reviewer WARNING。）\n- **C005**: no-evidence 模型 eval 必须传 --no_evidence 参数，确保推理时使用 NO_EVIDENCE_SYSTEM_PROMPT 与训练一致（原因：plan_006 1.7B/8B no-evidence eval 漏传该参数，导致训练/推理提示词不匹配（模型被要求输出未训练过的 evidence 字段），结果全部无效。Reviewer critical #20。）\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\nLLaMA RSFT s42 with-evidence 2048 eval。服务器: rtx5090-4x。cuda:0。\n\n## 背景\nRSFT evidence tax matched@2048 control。验证 RSFT @2048 vs @1024 delta 是否 <1pp（RSFT 截断率低且对称）。\n\nLLaMA RSFT 需要 nested LoRA: base → merge SFT adapter → load RSFT adapter。\n- RSFT s42 @1024 结果：ign_f1=0.5714, no-evi ign_f1=0.5526, tax=-1.88pp\n\n## 关键路径查找\n\n1. ssh_read_only 查找 LLaMA RSFT s42 相关路径：\n```bash\necho \"=== BASE ===\" && ls -d /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B 2>/dev/null\necho \"=== SFT ADAPTER ===\" && ls -d /root/autodl-tmp/sft_output_llama_3_1_8b /root/autodl-tmp/sft_output_llama*s42* 2>/dev/null\necho \"=== RSFT ADAPTER ===\" && ls -d /root/autodl-tmp/rsft_output_llama*s42* /root/autodl-tmp/llama_rsft*s42* /root/autodl-tmp/rsft_output_llama* 2>/dev/null\necho \"=== PREVIOUS EVAL CMD ===\" && grep -r \"rsft.*s42.*eval\\|llama_rsft_s42\" ~/runs/faith-evidence-ie/*.log 2>/dev/null | head -5\n```\n\n2. 也检查 registry 中 llama_rsft_s42 或 eval_llama_rsft_s42 的 spec 获取之前的命令/路径：\n   用 read_registry 查找相关实验\n\n3. 构建 eval 命令，关键参数：\n   - --model_path 或 --adapter_path: RSFT adapter 路径\n   - --base_model: /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\n   - --sft_adapter: SFT s42 adapter 路径（用于 merge）\n   - --max_new_tokens 2048\n   - --no_evidence 不加（这是 with-evidence）\n   - --batch_size 1\n   - --seed 42\n   - --split dev\n   - --no-quantize\n   - 输出: /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048/\n\n4. submit_training_job 提交：\n   - exp_id: eval_llama_rsft_s42_with_evidence_2048\n   - server: rtx5090-4x\n   - gpu: cuda:0\n   - timeout_hours: 6\n\n5. update_registry：\n   - hypothesis: \"matched@2048 control: LLaMA RSFT s42 with-evi@2048。@1024 ign_f1=0.5714。预期 delta<1pp，验证 RSFT evidence tax 在 matched budget 下稳定。\"\n   - parent: llama_rsft_s42（或相关的 eval 实验）\n\n6. 验证启动\n\n## 输出\nPID, GPU 占用, adapter 路径, 完整命令\n"
}
````

---

### Runtime record

_source line 2 · 2026-05-21T02:45:27.312Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-21T02:45:27.312Z",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

## Round 1

76 recorded events

### User

_source line 3 · 2026-05-21T02:45:27.376Z_

&lt;project_context>
# 项目: faith-evidence-ie

## 运行环境
- 服务器名: rtx5090-4x
- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account="root"）
- SSH 连接命令: ssh rtx5090-4x  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/autodl-tmp/freige

## ⚠️ 活跃约束（必须遵守）

- **C001**: 提交 eval 前必须 nvidia-smi 确认目标 GPU 显存占用 < 2GB，否则不提交、换卡或等待（原因：本 session 已 5 次因 eval 提交到被占用 GPU 导致 OOM，修复 eval 也因此作废。eval 推理需要接近全部显存，与训练共享必然 OOM。） [来自 D064]
- **C002**: 提交训练/评估任务时必须在命令前设置 CUDA_VISIBLE_DEVICES=X，禁止依赖 device_map="auto" 自动分配 GPU（原因：plan_011 和 rsft_ced_s45_train_r3 两次因未设 CUDA_VISIBLE_DEVICES 导致 device_map="auto" 跨 GPU 分布，造成 OOM 和资源冲突。已知 bug 重复发生。）
- **C003**: 提交训练任务时必须在命令前设置 CUDA_VISIBLE_DEVICES=X，禁止依赖 device_map="auto" 自动分配 GPU（原因：plan_011 和 rsft_ced_s45_train_r3 均因未设 CUDA_VISIBLE_DEVICES 导致模型跨 GPU 分布，造成 OOM 或显存冲突。已重复发生两次。）
- **C004**: Registry 标记 killed 时必须同时 kill -9 PID 并 ps 验证进程已终止，否则 killed 状态不可信（原因：rsft_ced_s45_train_r2 (PID 276148) registry 标记 killed 但进程未实际终止，占用 cuda:2 31.6GB 导致 r3 OOM。plan_011 也有类似模式。Reviewer WARNING。）
- **C005**: no-evidence 模型 eval 必须传 --no_evidence 参数，确保推理时使用 NO_EVIDENCE_SYSTEM_PROMPT 与训练一致（原因：plan_006 1.7B/8B no-evidence eval 漏传该参数，导致训练/推理提示词不匹配（模型被要求输出未训练过的 evidence 字段），结果全部无效。Reviewer critical #20。）


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
LLaMA RSFT s42 with-evidence 2048 eval。服务器: rtx5090-4x。cuda:0。

## 背景
RSFT evidence tax matched@2048 control。验证 RSFT @2048 vs @1024 delta 是否 <1pp（RSFT 截断率低且对称）。

LLaMA RSFT 需要 nested LoRA: base → merge SFT adapter → load RSFT adapter。
- RSFT s42 @1024 结果：ign_f1=0.5714, no-evi ign_f1=0.5526, tax=-1.88pp

## 关键路径查找

1. ssh_read_only 查找 LLaMA RSFT s42 相关路径：
```bash
echo "=== BASE ===" && ls -d /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B 2>/dev/null
echo "=== SFT ADAPTER ===" && ls -d /root/autodl-tmp/sft_output_llama_3_1_8b /root/autodl-tmp/sft_output_llama*s42* 2>/dev/null
echo "=== RSFT ADAPTER ===" && ls -d /root/autodl-tmp/rsft_output_llama*s42* /root/autodl-tmp/llama_rsft*s42* /root/autodl-tmp/rsft_output_llama* 2>/dev/null
echo "=== PREVIOUS EVAL CMD ===" && grep -r "rsft.*s42.*eval\|llama_rsft_s42" ~/runs/faith-evidence-ie/*.log 2>/dev/null | head -5
```

2. 也检查 registry 中 llama_rsft_s42 或 eval_llama_rsft_s42 的 spec 获取之前的命令/路径：
   用 read_registry 查找相关实验

3. 构建 eval 命令，关键参数：
   - --model_path 或 --adapter_path: RSFT adapter 路径
   - --base_model: /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B
   - --sft_adapter: SFT s42 adapter 路径（用于 merge）
   - --max_new_tokens 2048
   - --no_evidence 不加（这是 with-evidence）
   - --batch_size 1
   - --seed 42
   - --split dev
   - --no-quantize
   - 输出: /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048/

4. submit_training_job 提交：
   - exp_id: eval_llama_rsft_s42_with_evidence_2048
   - server: rtx5090-4x
   - gpu: cuda:0
   - timeout_hours: 6

5. update_registry：
   - hypothesis: "matched@2048 control: LLaMA RSFT s42 with-evi@2048。@1024 ign_f1=0.5714。预期 delta<1pp，验证 RSFT evidence tax 在 matched budget 下稳定。"
   - parent: llama_rsft_s42（或相关的 eval 实验）

6. 验证启动

## 输出
PID, GPU 占用, adapter 路径, 完整命令


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "17b9872f-b5ec-4de8-8f67-4b63afb166df",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-21T02:45:27.376Z_

```json
{
  "parentUuid": "17b9872f-b5ec-4de8-8f67-4b63afb166df",
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
      "mcp__agent-ml-research__detect_image",
      "mcp__agent-ml-research__kill_job",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__ssh_read_only",
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
      "mcp__agent-ml-research__detect_image",
      "mcp__agent-ml-research__kill_job",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__update_registry"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "207f7f62-9cb5-4a4b-a2d7-d8a58e10ce07",
  "timestamp": "2026-05-21T02:45:27.376Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-21T02:45:27.376Z_

```json
{
  "parentUuid": "207f7f62-9cb5-4a4b-a2d7-d8a58e10ce07",
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
  "uuid": "423777ec-f8a1-4ee0-ba56-623b547ebaa6",
  "timestamp": "2026-05-21T02:45:27.376Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-21T02:45:27.376Z_

```json
{
  "parentUuid": "423777ec-f8a1-4ee0-ba56-623b547ebaa6",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "671fd22b-7dbd-4ff3-9c5b-5c895929059e",
  "timestamp": "2026-05-21T02:45:27.376Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
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
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Assistant

_source line 8 · 2026-05-21T02:45:31.669Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to run an eval for LLaMA RSFT s42 with-evidence at 2048 max_new_tokens on cuda:0 of rtx5090-4x. Let me start by:

1. Checking GPU status on cuda:0
2. Finding relevant paths (base model, SFT adapter, RSFT adapter)
3. Checking registry for previous related experiments

Let me do these in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "671fd22b-7dbd-4ff3-9c5b-5c895929059e",
  "isSidechain": false,
  "requestId": "req_011CbEwv92zuos1QfLuxJNSY",
  "type": "assistant",
  "uuid": "df747812-0b54-4d8f-ad09-f835c4acfeb7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019JzCMPhkCpaivFSBfr1XHu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12820,
      "cache_read_input_tokens": 11841,
      "output_tokens": 229,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12820,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 229,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12820,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12820
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-21T02:45:32.337Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01FFW3ip6z9seRnfe3qWMqoZ`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__detect_image",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "df747812-0b54-4d8f-ad09-f835c4acfeb7",
  "isSidechain": false,
  "requestId": "req_011CbEwv92zuos1QfLuxJNSY",
  "type": "assistant",
  "uuid": "e478b8ca-3cd1-42ef-a17f-ddf34df40bf8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019JzCMPhkCpaivFSBfr1XHu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12820,
      "cache_read_input_tokens": 11841,
      "output_tokens": 229,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12820,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 229,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12820,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12820
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-21T02:45:32.360Z_

<details><summary>↩ Tool result · `toolu_01FFW3ip6z9seRnfe3qWMqoZ`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_read_only"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__detect_image"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e478b8ca-3cd1-42ef-a17f-ddf34df40bf8",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "e545a21a-1475-488c-99f7-a7b2f222a9c8",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__detect_image"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__detect_image",
    "total_deferred_tools": 26
  },
  "sourceToolAssistantUUID": "e478b8ca-3cd1-42ef-a17f-ddf34df40bf8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-21T02:45:35.362Z_

先检查 GPU 状态、查找路径、查 registry。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e545a21a-1475-488c-99f7-a7b2f222a9c8",
  "isSidechain": false,
  "requestId": "req_011CbEwvWMuCHEVtJPvu168o",
  "type": "assistant",
  "uuid": "ea9f3b5b-f2ba-4aa8-abd7-aa2259bd8a3c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLupKU413rHCwUPf9XZDUZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1087,
      "cache_read_input_tokens": 24661,
      "output_tokens": 524,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1087,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 524,
          "cache_read_input_tokens": 24661,
          "cache_creation_input_tokens": 1087,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1087
          },
          "type": "message"
        }
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

_source line 12 · 2026-05-21T02:45:36.315Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01NetKHVgWfTxTFWAE27GNe5`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "nvidia-smi --query-gpu=index,memory.used,memory.total --format=csv,noheader",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ea9f3b5b-f2ba-4aa8-abd7-aa2259bd8a3c",
  "isSidechain": false,
  "requestId": "req_011CbEwvWMuCHEVtJPvu168o",
  "type": "assistant",
  "uuid": "dafa67ac-efd0-433c-bd13-166988bcea10",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLupKU413rHCwUPf9XZDUZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1087,
      "cache_read_input_tokens": 24661,
      "output_tokens": 524,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1087,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 524,
          "cache_read_input_tokens": 24661,
          "cache_creation_input_tokens": 1087,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1087
          },
          "type": "message"
        }
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

_source line 13 · 2026-05-21T02:45:37.506Z_

<details><summary>↩ Tool result · `toolu_01NetKHVgWfTxTFWAE27GNe5`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"0, 0 MiB, 97887 MiB\\n1, 0 MiB, 97887 MiB\\n2, 18879 MiB, 97887 MiB\\n3, 18879 MiB, 97887 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.17}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dafa67ac-efd0-433c-bd13-166988bcea10",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "f714300c-94a4-448e-806d-c93ce28211da",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"0, 0 MiB, 97887 MiB\\\\n1, 0 MiB, 97887 MiB\\\\n2, 18879 MiB, 97887 MiB\\\\n3, 18879 MiB, 97887 MiB\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.17}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"0, 0 MiB, 97887 MiB\\n1, 0 MiB, 97887 MiB\\n2, 18879 MiB, 97887 MiB\\n3, 18879 MiB, 97887 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.17}}"
    }
  },
  "sourceToolAssistantUUID": "dafa67ac-efd0-433c-bd13-166988bcea10",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-21T02:45:37.729Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01AfJLmkSXR7TSQvyRtZntRQ`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls -d /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B /root/autodl-tmp/sft_output_llama* /root/autodl-tmp/rsft_output_llama* /root/autodl-tmp/llama_rsft* 2>/dev/null",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f714300c-94a4-448e-806d-c93ce28211da",
  "isSidechain": false,
  "requestId": "req_011CbEwvWMuCHEVtJPvu168o",
  "type": "assistant",
  "uuid": "ca7fd955-cb80-42c5-9d73-c178b2444574",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLupKU413rHCwUPf9XZDUZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1087,
      "cache_read_input_tokens": 24661,
      "output_tokens": 524,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1087,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 524,
          "cache_read_input_tokens": 24661,
          "cache_creation_input_tokens": 1087,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1087
          },
          "type": "message"
        }
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

_source line 15 · 2026-05-21T02:45:37.755Z_

<details><summary>↩ Tool result · `toolu_01AfJLmkSXR7TSQvyRtZntRQ`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ca7fd955-cb80-42c5-9d73-c178b2444574",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "e0e52939-46b6-4eb4-9a9b-c0cb08fad859",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "ca7fd955-cb80-42c5-9d73-c178b2444574",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-21T02:45:38.698Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01UBSkBxbwAsPxK8Wjc5YfeZ`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "exp_id": "eval_llama_rsft_s42_with_evidence_1024"
  },
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
  "parentUuid": "e0e52939-46b6-4eb4-9a9b-c0cb08fad859",
  "isSidechain": false,
  "requestId": "req_011CbEwvWMuCHEVtJPvu168o",
  "type": "assistant",
  "uuid": "c0a9c793-23fb-45e6-bb71-15d17528b6dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLupKU413rHCwUPf9XZDUZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1087,
      "cache_read_input_tokens": 24661,
      "output_tokens": 524,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1087,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 524,
          "cache_read_input_tokens": 24661,
          "cache_creation_input_tokens": 1087,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1087
          },
          "type": "message"
        }
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

_source line 17 · 2026-05-21T02:45:39.061Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01CBtCfqpf9QATfVJjnba3NS`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "exp_id": "llama_rsft_s42"
  },
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
  "parentUuid": "c0a9c793-23fb-45e6-bb71-15d17528b6dd",
  "isSidechain": false,
  "requestId": "req_011CbEwvWMuCHEVtJPvu168o",
  "type": "assistant",
  "uuid": "411ce7e5-16cb-429b-af19-c90ad520047f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLupKU413rHCwUPf9XZDUZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1087,
      "cache_read_input_tokens": 24661,
      "output_tokens": 524,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1087,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 524,
          "cache_read_input_tokens": 24661,
          "cache_creation_input_tokens": 1087,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1087
          },
          "type": "message"
        }
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

_source line 18 · 2026-05-21T02:45:39.825Z_

<details><summary>↩ Tool result · `toolu_01UBSkBxbwAsPxK8Wjc5YfeZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.1002}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c0a9c793-23fb-45e6-bb71-15d17528b6dd",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "2a46fdcc-0a0d-4440-8c16-2a2351780a5a",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.1002}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.1002}}"
    }
  },
  "sourceToolAssistantUUID": "c0a9c793-23fb-45e6-bb71-15d17528b6dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-21T02:45:40.829Z_

<details><summary>↩ Tool result · `toolu_01CBtCfqpf9QATfVJjnba3NS`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9791}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "411ce7e5-16cb-429b-af19-c90ad520047f",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "5f800f52-b6f3-4863-9f9d-b78acf507a06",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9791}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9791}}"
    }
  },
  "sourceToolAssistantUUID": "411ce7e5-16cb-429b-af19-c90ad520047f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
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
  "leafUuid": "5f800f52-b6f3-4863-9f9d-b78acf507a06",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Assistant

_source line 22 · 2026-05-21T02:45:43.997Z_

cuda:0 空闲（0 MiB）。路径查找命令被 `>` 阻断，registry 没找到精确匹配。重新查路径和 registry。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5f800f52-b6f3-4863-9f9d-b78acf507a06",
  "isSidechain": false,
  "requestId": "req_011CbEww8YG9aF4PxwCkSbc4",
  "type": "assistant",
  "uuid": "75ee2ecf-2b99-41b7-8419-39373937ed55",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TXcR6VK4dS6VGRS5ahbEsZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 25748,
      "output_tokens": 455,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 455,
          "cache_read_input_tokens": 25748,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
          },
          "type": "message"
        }
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

_source line 23 · 2026-05-21T02:45:45.030Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01EnWQsUZKvXaYPC1Lmj9WjR`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls -d /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "75ee2ecf-2b99-41b7-8419-39373937ed55",
  "isSidechain": false,
  "requestId": "req_011CbEww8YG9aF4PxwCkSbc4",
  "type": "assistant",
  "uuid": "35ef7571-0382-4419-88a4-024919853808",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TXcR6VK4dS6VGRS5ahbEsZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 25748,
      "output_tokens": 455,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 455,
          "cache_read_input_tokens": 25748,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-21T02:45:45.493Z_

<details><summary>↩ Tool result · `toolu_01EnWQsUZKvXaYPC1Lmj9WjR`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "35ef7571-0382-4419-88a4-024919853808",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "8ed95380-ded2-467d-9ec9-124db6f49e03",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.44}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"
    }
  },
  "sourceToolAssistantUUID": "35ef7571-0382-4419-88a4-024919853808",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-21T02:45:46.479Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_018YUEfMSsUiroNzMBhbCkkY`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "find /root/autodl-tmp -maxdepth 1 -type d -name \"*sft*llama*\" -o -name \"*llama*sft*\" -o -name \"*rsft*llama*\" -o -name \"*llama*rsft*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ed95380-ded2-467d-9ec9-124db6f49e03",
  "isSidechain": false,
  "requestId": "req_011CbEww8YG9aF4PxwCkSbc4",
  "type": "assistant",
  "uuid": "9b0ec47e-ea5c-4a14-bbb1-df90e2368d30",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TXcR6VK4dS6VGRS5ahbEsZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 25748,
      "output_tokens": 455,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 455,
          "cache_read_input_tokens": 25748,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
          },
          "type": "message"
        }
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

_source line 26 · 2026-05-21T02:45:46.929Z_

<details><summary>↩ Tool result · `toolu_018YUEfMSsUiroNzMBhbCkkY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/rsft_candidates_llama_3_1_8b\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\\n/root/autodl-tmp/rsft_scored_llama_3_1_8b\\n/root/autodl-tmp/rsft_scored_llama_3_1_8b_k1\\n/root/autodl-tmp/sft_output_llama_3_1_8b\\n/root/autodl-tmp/sft_output_llama_3_1_8b_no_evidence\\n/root/autodl-tmp/sft_output_llama_3_1_8b_s43\\n/root/autodl-tmp/sft_output_llama_3_1_8b_s44\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9b0ec47e-ea5c-4a14-bbb1-df90e2368d30",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "fb30e6c7-5748-4c1d-bb1d-486826b82000",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/rsft_candidates_llama_3_1_8b\\\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\\\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\\\\n/root/autodl-tmp/rsft_scored_llama_3_1_8b\\\\n/root/autodl-tmp/rsft_scored_llama_3_1_8b_k1\\\\n/root/autodl-tmp/sft_output_llama_3_1_8b\\\\n/root/autodl-tmp/sft_output_llama_3_1_8b_no_evidence\\\\n/root/autodl-tmp/sft_output_llama_3_1_8b_s43\\\\n/root/autodl-tmp/sft_output_llama_3_1_8b_s44\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.44}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/rsft_candidates_llama_3_1_8b\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s43\\n/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\\n/root/autodl-tmp/rsft_scored_llama_3_1_8b\\n/root/autodl-tmp/rsft_scored_llama_3_1_8b_k1\\n/root/autodl-tmp/sft_output_llama_3_1_8b\\n/root/autodl-tmp/sft_output_llama_3_1_8b_no_evidence\\n/root/autodl-tmp/sft_output_llama_3_1_8b_s43\\n/root/autodl-tmp/sft_output_llama_3_1_8b_s44\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"
    }
  },
  "sourceToolAssistantUUID": "9b0ec47e-ea5c-4a14-bbb1-df90e2368d30",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-21T02:45:47.385Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01WG1ETrSN34gRrLFJ4eFtdp`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "spec",
    "metrics",
    "status"
  ],
  "limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fb30e6c7-5748-4c1d-bb1d-486826b82000",
  "isSidechain": false,
  "requestId": "req_011CbEww8YG9aF4PxwCkSbc4",
  "type": "assistant",
  "uuid": "7f6fefbb-16ac-4f45-ad37-9d69f70b9ee1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TXcR6VK4dS6VGRS5ahbEsZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1024,
      "cache_read_input_tokens": 25748,
      "output_tokens": 455,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1024,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 455,
          "cache_read_input_tokens": 25748,
          "cache_creation_input_tokens": 1024,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1024
          },
          "type": "message"
        }
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

_source line 28 · 2026-05-21T02:45:48.354Z_

<details><summary>↩ Tool result · `toolu_01WG1ETrSN34gRrLFJ4eFtdp`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan017_14b_rsft_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-14B + SFT(checkpoint-144) + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 53413, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"32503 MiB\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"base_model\": \"/root/autodl-tmp/models/Qwen/Qwen3-14B\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\", \"log_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\"}, \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.5886, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 0, \"evi_f1\": 0.8392, \"edcr\": 0.5396}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"58417\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\", \"submitted_at\": \"2026-05-20T22:29:47.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\", \"wall_clock_seconds\": 15226.5, \"gpu_hours\": 4.23}, \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987}}, \"eval_llama_sft_s42_with_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\", \"pid\": 55468, \"gpu\": \"cuda:3\"}, \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}}, \"plan017_14b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": null, \"model_name\": \"Qwen3-14B + SFT ckpt-144 + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b/\", \"eval_data\": \"docred dev split\", \"pid\": 55039, \"gpu\": \"cuda:2\"}, \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}}, \"eval_llama_sft_s43_no_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"45587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T18:26:31.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14418.9, \"gpu_hours\": 4.01}}, \"eval_llama_sft_s42_no_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"42346\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:41:22.540Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12923.2, \"gpu_hours\": 3.59}, \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\"}}, \"plan017_14b_rsft_generate_r4\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"36398\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\", \"submitted_at\": \"2026-05-20T16:13:11.226Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\", \"wall_clock_seconds\": 18025.3, \"gpu_hours\": 5.01}, \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}}, \"eval_llama_sft_s44_no_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"40255\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:07:29.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14763.9, \"gpu_hours\": 4.1}, \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\"}}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}, \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"plan017_14b_rsft_train\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"48806\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\", \"submitted_at\": \"2026-05-20T19:16:50Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"data_count\": 3015, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_14b\", \"wall_clock_seconds\": 5575.6, \"gpu_hours\": 1.55}, \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\"}}, \"plan017_14b_ced_scoring\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"44419\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\", \"submitted_at\": \"2026-05-20T18:10:17.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_14b\", \"wall_clock_seconds\": 3793.4, \"gpu_hours\": 1.05}, \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}}, \"eval_llama_sft_s44_no_evidence\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\"}, \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}}, \"eval_llama_rsft_s44_no_evidence\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"edcr\": 0.6818, \"format_ok\": 984, \"n_documents\": 985, \"format_compliance\": 0.999, \"n_truncated\": 178}}, \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"27322\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\", \"submitted_at\": \"2026-05-20T14:08:24.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7282.5, \"gpu_hours\": 2.02}}, \"migration_bjb2_to_westd\": {\"status\": \"DONE\", \"spec\": {\"command\": \"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/\", \"data_count\": 207, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/\", \"log_path\": \"/tmp/rsync_progress_reporter.sh\"}}, \"plan017_14b_rsft_generate_r3\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17644\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\", \"submitted_at\": \"2026-05-20T11:35:24.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13307.5, \"gpu_hours\": 3.7}}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"16978\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\", \"submitted_at\": \"2026-05-20T11:31:12.890Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11295.5, \"gpu_hours\": 3.14}, \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}}, \"llama_sft_s44_train_eval_r3\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"16658\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\", \"submitted_at\": \"2026-05-20T11:30:48.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11252.9, \"gpu_hours\": 3.13}, \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"status\": \"DONE\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu_model\": \"RTX PRO 6000 Blackwell 98GB\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\"}, \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17267\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\", \"submitted_at\": \"2026-05-20T11:31:24.677Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 38.7, \"gpu_hours\": 0.01}}, \"eval_llama_sft_s42_no_evidence_std\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"llama_sft_s44_train_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"754497\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:57.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.0, \"gpu_hours\": 3.03}}, \"llama_sft_s43_train_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"754413\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:54.309Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.3, \"gpu_hours\": 3.03}}, \"plan017_14b_rsft_generate\": {\"status\": \"DONE\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"llama_sft_s44_train_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"753525\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\", \"submitted_at\": \"2026-05-20T04:21:19.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 590.1, \"gpu_hours\": 0.16}}, \"llama_sft_s43_train_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"753922\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\", \"submitted_at\": \"2026-05-20T04:25:41.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 325.6, \"gpu_hours\": 0.09}}}, \"count\": 30, \"total\": 290, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9497}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7f6fefbb-16ac-4f45-ad37-9d69f70b9ee1",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "9bc47270-168f-49ec-87ef-c2acb4c55aeb",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan017_14b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-14B + SFT(checkpoint-144) + RSFT\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_14b\\\", \\\"eval_data\\\": \\\"DocRED dev set (985 docs, 12275 gold triples)\\\", \\\"pid\\\": 53413, \\\"gpu\\\": \\\"cuda:0\\\", \\\"gpu_mem_used\\\": \\\"32503 MiB\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"base_model\\\": \\\"/root/autodl-tmp/models/Qwen/Qwen3-14B\\\", \\\"nested_lora\\\": true, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5886, \\\"f1\\\": 0.5886, \\\"format_ok\\\": 985, \\\"format_ok_rate\\\": 1, \\\"truncated\\\": 0, \\\"evi_f1\\\": 0.8392, \\\"edcr\\\": 0.5396}}, \\\"eval_llama_sft_s43_no_evidence_2048_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"58417\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T22:29:47.154Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\\\", \\\"wall_clock_seconds\\\": 15226.5, \\\"gpu_hours\\\": 4.23}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3389, \\\"f1\\\": 0.3575, \\\"format_ok\\\": 834, \\\"format_ok_rate\\\": 0.8467, \\\"truncated\\\": 359, \\\"predictions\\\": 23070, \\\"inference_time_seconds\\\": 14987}}, \\\"eval_llama_sft_s42_with_evidence_2048\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\\\", \\\"pid\\\": 55468, \\\"gpu\\\": \\\"cuda:3\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5649, \\\"f1\\\": 0.5767, \\\"format_ok\\\": 976, \\\"format_ok_rate\\\": 0.9909, \\\"truncated\\\": 147, \\\"predictions\\\": 20302, \\\"evi_f1\\\": 0.803, \\\"edcr\\\": 0.6428, \\\"inference_time_seconds\\\": 10491.7}}, \\\"plan017_14b_rsft_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": null, \\\"model_name\\\": \\\"Qwen3-14B + SFT ckpt-144 + RSFT\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_14b/\\\", \\\"eval_data\\\": \\\"docred dev split\\\", \\\"pid\\\": 55039, \\\"gpu\\\": \\\"cuda:2\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5432, \\\"f1\\\": 0.5536, \\\"ign_precision\\\": 0.5193, \\\"ign_recall\\\": 0.5693, \\\"precision\\\": 0.5414, \\\"recall\\\": 0.5664, \\\"evi_f1\\\": 0, \\\"edcr\\\": 0, \\\"format_ok\\\": 953, \\\"format_ok_rate\\\": 0.9675, \\\"n_total\\\": 985, \\\"n_predictions\\\": 15333, \\\"n_truncated\\\": 106, \\\"tp\\\": 6882, \\\"pred_count\\\": 12711, \\\"gold_count\\\": 12151, \\\"inference_time_seconds\\\": 9427.5}}, \\\"eval_llama_sft_s43_no_evidence_2048\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"45587\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T18:26:31.570Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 14418.9, \\\"gpu_hours\\\": 4.01}}, \\\"eval_llama_sft_s42_no_evidence_2048\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"42346\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T17:41:22.540Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 12923.2, \\\"gpu_hours\\\": 3.59}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.521, \\\"f1\\\": 0.5306, \\\"ign_precision\\\": 0.5342, \\\"ign_recall\\\": 0.5085, \\\"format_ok_rate\\\": 0.8873, \\\"n_format_ok\\\": 874, \\\"n_truncated\\\": 201, \\\"truncation_rate\\\": 0.2041, \\\"n_predictions\\\": 23031, \\\"n_documents\\\": 985, \\\"pred_count_dedup\\\": 11109, \\\"fair_tax_pp\\\": 1.2, \\\"fair_subset_docs\\\": 873, \\\"fair_with_evi_ign_f1\\\": 0.5443, \\\"fair_no_evi_ign_f1\\\": 0.5564, \\\"raw_tax_pp\\\": -1.74, \\\"vs_1024_ign_f1_delta\\\": \\\"-0.09pp\\\", \\\"vs_1024_format_ok_delta\\\": \\\"0pp (874→874)\\\", \\\"vs_1024_fair_tax_delta\\\": \\\"-0.14pp (+1.34→+1.20)\\\"}}, \\\"plan017_14b_rsft_generate_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\\\", \\\"metrics\\\": {\\\"total_lines\\\": 24216, \\\"unique_docs\\\": 3027, \\\"generations_per_doc\\\": 8}}, \\\"metrics\\\": {\\\"total_lines\\\": 24216, \\\"unique_docs\\\": 3027, \\\"generations_per_doc\\\": 8}}, \\\"eval_llama_sft_s43_no_evidence_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"36398\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T16:13:11.226Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\", \\\"wall_clock_seconds\\\": 18025.3, \\\"gpu_hours\\\": 5.01}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3391, \\\"format_compliance\\\": 0.616, \\\"n_truncated\\\": 378}}, \\\"eval_llama_sft_s44_no_evidence_2048\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"40255\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T17:07:29.962Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 14763.9, \\\"gpu_hours\\\": 4.1}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.4373, \\\"f1\\\": 0.4504, \\\"ign_precision\\\": 0.3947, \\\"ign_recall\\\": 0.4902, \\\"format_ok_rate\\\": 0.9919, \\\"n_format_ok\\\": 977, \\\"n_truncated\\\": 246, \\\"truncation_rate\\\": 0.2497, \\\"n_predictions\\\": 28366, \\\"n_documents\\\": 985, \\\"fair_tax_pp\\\": -4.18, \\\"fair_subset_docs\\\": 977, \\\"fair_with_evi_ign_f1\\\": 0.4813, \\\"fair_no_evi_ign_f1\\\": 0.4395, \\\"vs_1024_ign_f1_delta\\\": \\\"+10.47pp\\\", \\\"vs_1024_truncation_delta\\\": \\\"-16.7pp\\\"}}, \\\"d112_rsft_s44_ced_score\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 604576, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-base\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44\\\", \\\"output_samples\\\": 3014, \\\"note\\\": \\\"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\\\"}, \\\"metrics\\\": {\\\"total_scored\\\": 24216, \\\"selected_count\\\": 3014, \\\"selection_rate\\\": 0.124, \\\"mean_f1\\\": 0.676, \\\"mean_ced\\\": 0.676}}, \\\"plan017_14b_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"48806\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T19:16:50Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\\\", \\\"data_count\\\": 3015, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_14b\\\", \\\"wall_clock_seconds\\\": 5575.6, \\\"gpu_hours\\\": 1.55}, \\\"metrics\\\": {\\\"train_loss\\\": 0.5005, \\\"mean_token_accuracy\\\": 0.8783, \\\"total_steps\\\": 1131, \\\"runtime_seconds\\\": 3958}}, \\\"d112_rsft_s44_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 584466, \\\"tmux_session\\\": \\\"d112_rsft_s44_generate\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\", \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"top_p\\\": 0.95, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\"}}, \\\"plan017_14b_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"44419\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T18:10:17.337Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_14b\\\", \\\"wall_clock_seconds\\\": 3793.4, \\\"gpu_hours\\\": 1.05}, \\\"metrics\\\": {\\\"total_scored\\\": 24216, \\\"unique_docs_total\\\": 3027, \\\"selected_count\\\": 3015, \\\"unique_docs_selected\\\": 3015, \\\"selection_rate\\\": 0.1245, \\\"all_mean_f1\\\": 0.616, \\\"all_mean_ced\\\": 0.568, \\\"all_mean_combined\\\": 0.673, \\\"selected_mean_f1\\\": 0.73, \\\"selected_mean_ced\\\": 0.69, \\\"selected_mean_combined\\\": 0.768, \\\"selected_median_f1\\\": 0.75, \\\"selected_median_ced\\\": 0.71, \\\"f1_filter_dropped_gens\\\": 497, \\\"f1_filter_dropped_docs\\\": 12, \\\"truncated_count\\\": 1701, \\\"truncated_ratio\\\": 0.07, \\\"truncated_mean_f1\\\": 0.487, \\\"non_truncated_mean_f1\\\": 0.625, \\\"truncation_f1_gap\\\": 0.139, \\\"format_reward_mean\\\": 0.9996, \\\"output_file\\\": \\\"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\\\", \\\"output_size_mb\\\": 9.1, \\\"runtime_hours\\\": 1}}, \\\"eval_llama_sft_s44_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3326, \\\"f1\\\": 0.3348, \\\"format_compliance\\\": 0.945, \\\"format_ok\\\": 931, \\\"n_documents\\\": 985, \\\"n_truncated\\\": 411}}, \\\"eval_llama_rsft_s44_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\\\", \\\"metrics\\\": {\\\"ign_f1\\\": 0.555, \\\"f1\\\": 0.5674, \\\"edcr\\\": 0.6818, \\\"format_ok\\\": 984, \\\"n_documents\\\": 985, \\\"format_compliance\\\": 0.999, \\\"n_truncated\\\": 178}}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.555, \\\"f1\\\": 0.5674, \\\"evi_f1\\\": 0.001, \\\"evi_f1_joint\\\": 0.0001, \\\"edcr\\\": 0.6818, \\\"format_compliance\\\": 0.999, \\\"n_truncated\\\": 178, \\\"n_predictions\\\": 18089, \\\"inference_time_s\\\": 6555.2, \\\"n_documents\\\": 985, \\\"n_format_ok\\\": 984}}, \\\"eval_llama_sft_s43_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"27322\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T14:08:24.174Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 7282.5, \\\"gpu_hours\\\": 2.02}}, \\\"migration_bjb2_to_westd\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/\\\", \\\"data_count\\\": 207, \\\"model_name\\\": \\\"N/A\\\", \\\"seed\\\": 0, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/\\\", \\\"log_path\\\": \\\"/tmp/rsync_progress_reporter.sh\\\"}}, \\\"plan017_14b_rsft_generate_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"17644\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:35:24.818Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 13307.5, \\\"gpu_hours\\\": 3.7}}, \\\"eval_llama_sft_s42_no_evidence_std_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"16978\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:31:12.890Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 11295.5, \\\"gpu_hours\\\": 3.14}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5219, \\\"f1\\\": 0.5311, \\\"ign_precision\\\": 0.542, \\\"ign_recall\\\": 0.5031, \\\"evi_f1_joint\\\": 0.0005, \\\"evi_f1_tp\\\": 0.0102, \\\"edcr\\\": 0.58, \\\"format_ok_rate\\\": 0.8873, \\\"n_truncated\\\": 219, \\\"n_predictions\\\": 16292, \\\"inference_time_seconds\\\": 6927.2}}, \\\"llama_sft_s44_train_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"16658\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:30:48.150Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 11252.9, \\\"gpu_hours\\\": 3.13}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.4802, \\\"rel_f1\\\": 0.4902, \\\"evi_f1_joint\\\": 0.3913, \\\"evi_f1_tp\\\": 0.8502, \\\"edcr\\\": 0.6579, \\\"format_ok\\\": \\\"985/985\\\", \\\"n_truncated\\\": 240, \\\"n_predictions\\\": 14990}}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"516711\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:33.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5362.4, \\\"gpu_hours\\\": 1.49}, \\\"metrics\\\": {\\\"train_loss\\\": 0.3862, \\\"mean_token_accuracy\\\": 0.8735, \\\"epochs\\\": 3, \\\"global_steps\\\": 1134, \\\"runtime_seconds\\\": 2894.88, \\\"data_samples\\\": 3018, \\\"ign_f1\\\": 0.5471, \\\"rel_f1\\\": 0.5651, \\\"evi_f1\\\": 0.818, \\\"edcr\\\": 0.6094, \\\"num_preds\\\": 16226, \\\"truncated\\\": \\\"231/985\\\", \\\"format_ok\\\": \\\"985/985\\\"}}, \\\"d102_8b_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"516605\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:29.717Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5361.8, \\\"gpu_hours\\\": 1.49}, \\\"metrics\\\": {\\\"train_loss\\\": 0.3877, \\\"mean_token_accuracy\\\": 0.8579, \\\"epochs\\\": 3, \\\"global_steps\\\": 1134, \\\"runtime_seconds\\\": 2915.82, \\\"entropy\\\": 0.5847, \\\"data_samples\\\": 3018}}, \\\"llama_sft_s43_train_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_model\\\": \\\"RTX PRO 6000 Blackwell 98GB\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5142, \\\"evi_f1_joint\\\": 0.422, \\\"evi_f1_tp\\\": 0.8245, \\\"edcr\\\": 0.5866, \\\"re_p_ign\\\": 0.4917, \\\"re_r_ign\\\": 0.5389, \\\"train_loss_final\\\": 0.521}}, \\\"plan017_14b_rsft_generate_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"17267\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:31:24.677Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 38.7, \\\"gpu_hours\\\": 0.01}}, \\\"eval_llama_sft_s42_no_evidence_std\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 1000, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"llama_sft_s44_train_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"754497\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:31:57.230Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"wall_clock_seconds\\\": 10893.0, \\\"gpu_hours\\\": 3.03}}, \\\"llama_sft_s43_train_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"754413\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:31:54.309Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"wall_clock_seconds\\\": 10893.3, \\\"gpu_hours\\\": 3.03}}, \\\"plan017_14b_rsft_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\", \\\"cuda:2\\\"], \\\"pid\\\": \\\"712685\\\"}}, \\\"llama_sft_s44_train_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"753525\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:21:19.626Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"N/A - OOM\\\", \\\"wall_clock_seconds\\\": 590.1, \\\"gpu_hours\\\": 0.16}}, \\\"llama_sft_s43_train_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"753922\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:25:41.064Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"N/A - OOM\\\", \\\"wall_clock_seconds\\\": 325.6, \\\"gpu_hours\\\": 0.09}}}, \\\"count\\\": 30, \\\"total\\\": 290, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9497}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan017_14b_rsft_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-14B + SFT(checkpoint-144) + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 53413, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"32503 MiB\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"base_model\": \"/root/autodl-tmp/models/Qwen/Qwen3-14B\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\", \"log_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\"}, \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.5886, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 0, \"evi_f1\": 0.8392, \"edcr\": 0.5396}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"58417\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\", \"submitted_at\": \"2026-05-20T22:29:47.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\", \"wall_clock_seconds\": 15226.5, \"gpu_hours\": 4.23}, \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987}}, \"eval_llama_sft_s42_with_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\", \"pid\": 55468, \"gpu\": \"cuda:3\"}, \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}}, \"plan017_14b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": null, \"model_name\": \"Qwen3-14B + SFT ckpt-144 + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b/\", \"eval_data\": \"docred dev split\", \"pid\": 55039, \"gpu\": \"cuda:2\"}, \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}}, \"eval_llama_sft_s43_no_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"45587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T18:26:31.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14418.9, \"gpu_hours\": 4.01}}, \"eval_llama_sft_s42_no_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"42346\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:41:22.540Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12923.2, \"gpu_hours\": 3.59}, \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\"}}, \"plan017_14b_rsft_generate_r4\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"36398\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\", \"submitted_at\": \"2026-05-20T16:13:11.226Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\", \"wall_clock_seconds\": 18025.3, \"gpu_hours\": 5.01}, \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}}, \"eval_llama_sft_s44_no_evidence_2048\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"40255\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:07:29.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14763.9, \"gpu_hours\": 4.1}, \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\"}}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}, \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"plan017_14b_rsft_train\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"48806\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\", \"submitted_at\": \"2026-05-20T19:16:50Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"data_count\": 3015, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_14b\", \"wall_clock_seconds\": 5575.6, \"gpu_hours\": 1.55}, \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\"}}, \"plan017_14b_ced_scoring\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"44419\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\", \"submitted_at\": \"2026-05-20T18:10:17.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_14b\", \"wall_clock_seconds\": 3793.4, \"gpu_hours\": 1.05}, \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}}, \"eval_llama_sft_s44_no_evidence\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\"}, \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}}, \"eval_llama_rsft_s44_no_evidence\": {\"status\": \"DONE\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"edcr\": 0.6818, \"format_ok\": 984, \"n_documents\": 985, \"format_compliance\": 0.999, \"n_truncated\": 178}}, \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"27322\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\", \"submitted_at\": \"2026-05-20T14:08:24.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7282.5, \"gpu_hours\": 2.02}}, \"migration_bjb2_to_westd\": {\"status\": \"DONE\", \"spec\": {\"command\": \"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/\", \"data_count\": 207, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/\", \"log_path\": \"/tmp/rsync_progress_reporter.sh\"}}, \"plan017_14b_rsft_generate_r3\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17644\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\", \"submitted_at\": \"2026-05-20T11:35:24.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13307.5, \"gpu_hours\": 3.7}}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"16978\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\", \"submitted_at\": \"2026-05-20T11:31:12.890Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11295.5, \"gpu_hours\": 3.14}, \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}}, \"llama_sft_s44_train_eval_r3\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"16658\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\", \"submitted_at\": \"2026-05-20T11:30:48.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11252.9, \"gpu_hours\": 3.13}, \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"status\": \"DONE\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu_model\": \"RTX PRO 6000 Blackwell 98GB\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\"}, \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17267\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\", \"submitted_at\": \"2026-05-20T11:31:24.677Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 38.7, \"gpu_hours\": 0.01}}, \"eval_llama_sft_s42_no_evidence_std\": {\"status\": \"DONE\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"llama_sft_s44_train_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"754497\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:57.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.0, \"gpu_hours\": 3.03}}, \"llama_sft_s43_train_eval_r2\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"754413\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:54.309Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.3, \"gpu_hours\": 3.03}}, \"plan017_14b_rsft_generate\": {\"status\": \"DONE\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"llama_sft_s44_train_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"753525\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\", \"submitted_at\": \"2026-05-20T04:21:19.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 590.1, \"gpu_hours\": 0.16}}, \"llama_sft_s43_train_eval\": {\"status\": \"DONE\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"753922\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\", \"submitted_at\": \"2026-05-20T04:25:41.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 325.6, \"gpu_hours\": 0.09}}}, \"count\": 30, \"total\": 290, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9497}}"
    }
  },
  "sourceToolAssistantUUID": "7f6fefbb-16ac-4f45-ad37-9d69f70b9ee1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 29 · 2026-05-21T02:45:48.367Z_

```json
{
  "parentUuid": "9bc47270-168f-49ec-87ef-c2acb4c55aeb",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "e10fa8e0-f28e-4544-b0e3-b8a0d4ac5ff6",
  "timestamp": "2026-05-21T02:45:48.367Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 30_

```json
{
  "type": "last-prompt",
  "leafUuid": "e10fa8e0-f28e-4544-b0e3-b8a0d4ac5ff6",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Runtime record

_source line 31_

```json
{
  "type": "ai-title",
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Assistant

_source line 32 · 2026-05-21T02:46:08.714Z_

<details><summary>Logged reasoning block</summary>

```text
Let me analyze what I found:

1. **GPU status**: cuda:0 has 0 MiB used - good to go (C001 satisfied)
2. **Base model**: `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B` exists
3. **SFT adapter**: `/root/autodl-tmp/sft_output_llama_3_1_8b` (s42 default)


4. **RSFT adapter**: I'm checking the RSFT output directories to identify which one corresponds to the default s42 seed versus the s43 variant.

Looking at the registry entries, I notice the RSFT s44 eval command uses `--model_path rsft_output_llama_3_1_8b_k1_s44`, but I need to trace back what the actual base path structure is for s42. Let me examine the 14B RSFT inference command to understand the pattern better.

The 14B setup shows a nested LoRA configuration where `--model_path` points to the RSFT adapter, `--base_model` specifies the base model, and `--sft_adapter` points to the SFT checkpoint. But the s44 eval command seems to be using a simpler format with just the model path, so I need to figure out if that's a shorthand or if the structure is actually different.

Let me check what checkpoint exists in the LLaMA SFT output directory to match the pattern from the 14B version, and see if there's already an eval result at 1024 tokens for the LLaMA RSFT s42 variant with evidence included.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e10fa8e0-f28e-4544-b0e3-b8a0d4ac5ff6",
  "isSidechain": false,
  "requestId": "req_011CbEwwghHUQjSFbEveGipx",
  "type": "assistant",
  "uuid": "62eb4595-283d-49f5-ad48-a66105ec0ce1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0135DbeScBrE918hrxZVdbXY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15131,
      "cache_read_input_tokens": 26772,
      "output_tokens": 1395,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15131,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1395,
          "cache_read_input_tokens": 26772,
          "cache_creation_input_tokens": 15131,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15131
          },
          "type": "message"
        }
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

_source line 33 · 2026-05-21T02:46:09.271Z_

找到路径了。需要确认 SFT adapter 的 checkpoint 目录和 RSFT @1024 的 eval 记录。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "62eb4595-283d-49f5-ad48-a66105ec0ce1",
  "isSidechain": false,
  "requestId": "req_011CbEwwghHUQjSFbEveGipx",
  "type": "assistant",
  "uuid": "46d0dda2-dcdd-44bf-bb15-831ef2a32ac1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0135DbeScBrE918hrxZVdbXY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15131,
      "cache_read_input_tokens": 26772,
      "output_tokens": 1395,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15131,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1395,
          "cache_read_input_tokens": 26772,
          "cache_creation_input_tokens": 15131,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15131
          },
          "type": "message"
        }
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

_source line 34 · 2026-05-21T02:46:10.221Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01UxSNGcjhF5RdBhZbF1H9os`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls /root/autodl-tmp/sft_output_llama_3_1_8b/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "46d0dda2-dcdd-44bf-bb15-831ef2a32ac1",
  "isSidechain": false,
  "requestId": "req_011CbEwwghHUQjSFbEveGipx",
  "type": "assistant",
  "uuid": "fb40225c-cebb-45e4-8463-750997d0bc75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0135DbeScBrE918hrxZVdbXY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15131,
      "cache_read_input_tokens": 26772,
      "output_tokens": 1395,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15131,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1395,
          "cache_read_input_tokens": 26772,
          "cache_creation_input_tokens": 15131,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15131
          },
          "type": "message"
        }
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

_source line 35 · 2026-05-21T02:46:10.615Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01DPGLAn49Yqo4xQX2itB3Eo`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls /root/autodl-tmp/rsft_output_llama_3_1_8b_k1/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fb40225c-cebb-45e4-8463-750997d0bc75",
  "isSidechain": false,
  "requestId": "req_011CbEwwghHUQjSFbEveGipx",
  "type": "assistant",
  "uuid": "52d83d4b-7e4b-419b-91e3-fa128a11a362",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0135DbeScBrE918hrxZVdbXY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15131,
      "cache_read_input_tokens": 26772,
      "output_tokens": 1395,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15131,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1395,
          "cache_read_input_tokens": 26772,
          "cache_creation_input_tokens": 15131,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15131
          },
          "type": "message"
        }
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

_source line 36 · 2026-05-21T02:46:10.670Z_

<details><summary>↩ Tool result · `toolu_01UxSNGcjhF5RdBhZbF1H9os`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"README.md\\nadapter_config.json\\nadapter_model.safetensors\\nchat_template.jinja\\ncheckpoint-190\\ncheckpoint-570\\nspecial_tokens_map.json\\ntokenizer.json\\ntokenizer_config.json\\ntraining_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.43}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fb40225c-cebb-45e4-8463-750997d0bc75",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "d2fee352-69e1-4aae-9d49-7e976a205bf3",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"README.md\\\\nadapter_config.json\\\\nadapter_model.safetensors\\\\nchat_template.jinja\\\\ncheckpoint-190\\\\ncheckpoint-570\\\\nspecial_tokens_map.json\\\\ntokenizer.json\\\\ntokenizer_config.json\\\\ntraining_args.bin\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.43}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"README.md\\nadapter_config.json\\nadapter_model.safetensors\\nchat_template.jinja\\ncheckpoint-190\\ncheckpoint-570\\nspecial_tokens_map.json\\ntokenizer.json\\ntokenizer_config.json\\ntraining_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.43}}"
    }
  },
  "sourceToolAssistantUUID": "fb40225c-cebb-45e4-8463-750997d0bc75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 37 · 2026-05-21T02:46:11.206Z_

<details><summary>↩ Tool result · `toolu_01DPGLAn49Yqo4xQX2itB3Eo`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"README.md\\nadapter_config.json\\nadapter_model.safetensors\\nchat_template.jinja\\ncheckpoint-1100\\ncheckpoint-1107\\nspecial_tokens_map.json\\ntokenizer.json\\ntokenizer_config.json\\ntraining_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "52d83d4b-7e4b-419b-91e3-fa128a11a362",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "b63d409a-67c7-4fe1-a551-cdf314ed78bc",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"README.md\\\\nadapter_config.json\\\\nadapter_model.safetensors\\\\nchat_template.jinja\\\\ncheckpoint-1100\\\\ncheckpoint-1107\\\\nspecial_tokens_map.json\\\\ntokenizer.json\\\\ntokenizer_config.json\\\\ntraining_args.bin\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.53}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"README.md\\nadapter_config.json\\nadapter_model.safetensors\\nchat_template.jinja\\ncheckpoint-1100\\ncheckpoint-1107\\nspecial_tokens_map.json\\ntokenizer.json\\ntokenizer_config.json\\ntraining_args.bin\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.53}}"
    }
  },
  "sourceToolAssistantUUID": "52d83d4b-7e4b-419b-91e3-fa128a11a362",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-21T02:46:11.978Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_017g45ZRcm9X32jmY1Bui1Ki`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "spec",
    "metrics"
  ],
  "limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b63d409a-67c7-4fe1-a551-cdf314ed78bc",
  "isSidechain": false,
  "requestId": "req_011CbEwwghHUQjSFbEveGipx",
  "type": "assistant",
  "uuid": "c92e819f-c2d5-4feb-ab78-407debe76e2b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0135DbeScBrE918hrxZVdbXY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15131,
      "cache_read_input_tokens": 26772,
      "output_tokens": 1395,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15131,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1395,
          "cache_read_input_tokens": 26772,
          "cache_creation_input_tokens": 15131,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15131
          },
          "type": "message"
        }
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

_source line 39 · 2026-05-21T02:46:13.080Z_

<details><summary>↩ Tool result · `toolu_017g45ZRcm9X32jmY1Bui1Ki`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan017_14b_rsft_eval\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-14B + SFT(checkpoint-144) + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 53413, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"32503 MiB\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"base_model\": \"/root/autodl-tmp/models/Qwen/Qwen3-14B\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\", \"log_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\"}, \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.5886, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 0, \"evi_f1\": 0.8392, \"edcr\": 0.5396}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"58417\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\", \"submitted_at\": \"2026-05-20T22:29:47.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\", \"wall_clock_seconds\": 15226.5, \"gpu_hours\": 4.23}, \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987}}, \"eval_llama_sft_s42_with_evidence_2048\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\", \"pid\": 55468, \"gpu\": \"cuda:3\"}, \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}}, \"plan017_14b_rsft_no_evidence_eval\": {\"spec\": {\"command\": \"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": null, \"model_name\": \"Qwen3-14B + SFT ckpt-144 + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b/\", \"eval_data\": \"docred dev split\", \"pid\": 55039, \"gpu\": \"cuda:2\"}, \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}}, \"eval_llama_sft_s43_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"45587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T18:26:31.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14418.9, \"gpu_hours\": 4.01}}, \"eval_llama_sft_s42_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"42346\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:41:22.540Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12923.2, \"gpu_hours\": 3.59}, \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\"}}, \"plan017_14b_rsft_generate_r4\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"36398\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\", \"submitted_at\": \"2026-05-20T16:13:11.226Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\", \"wall_clock_seconds\": 18025.3, \"gpu_hours\": 5.01}, \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}}, \"eval_llama_sft_s44_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"40255\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:07:29.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14763.9, \"gpu_hours\": 4.1}, \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\"}}, \"d112_rsft_s44_ced_score\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}, \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"plan017_14b_rsft_train\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"48806\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\", \"submitted_at\": \"2026-05-20T19:16:50Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"data_count\": 3015, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_14b\", \"wall_clock_seconds\": 5575.6, \"gpu_hours\": 1.55}, \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}}, \"d112_rsft_s44_generate\": {\"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\"}}, \"plan017_14b_ced_scoring\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"44419\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\", \"submitted_at\": \"2026-05-20T18:10:17.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_14b\", \"wall_clock_seconds\": 3793.4, \"gpu_hours\": 1.05}, \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}}, \"eval_llama_sft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\"}, \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}}, \"eval_llama_rsft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"edcr\": 0.6818, \"format_ok\": 984, \"n_documents\": 985, \"format_compliance\": 0.999, \"n_truncated\": 178}}, \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"27322\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\", \"submitted_at\": \"2026-05-20T14:08:24.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7282.5, \"gpu_hours\": 2.02}}, \"migration_bjb2_to_westd\": {\"spec\": {\"command\": \"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/\", \"data_count\": 207, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/\", \"log_path\": \"/tmp/rsync_progress_reporter.sh\"}}, \"plan017_14b_rsft_generate_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17644\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\", \"submitted_at\": \"2026-05-20T11:35:24.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13307.5, \"gpu_hours\": 3.7}}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"16978\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\", \"submitted_at\": \"2026-05-20T11:31:12.890Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11295.5, \"gpu_hours\": 3.14}, \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}}, \"llama_sft_s44_train_eval_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"16658\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\", \"submitted_at\": \"2026-05-20T11:30:48.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11252.9, \"gpu_hours\": 3.13}, \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}}, \"d102_8b_rsft_k1_s43\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu_model\": \"RTX PRO 6000 Blackwell 98GB\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\"}, \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17267\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\", \"submitted_at\": \"2026-05-20T11:31:24.677Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 38.7, \"gpu_hours\": 0.01}}, \"eval_llama_sft_s42_no_evidence_std\": {\"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"llama_sft_s44_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"754497\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:57.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.0, \"gpu_hours\": 3.03}}, \"llama_sft_s43_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"754413\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:54.309Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.3, \"gpu_hours\": 3.03}}, \"plan017_14b_rsft_generate\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"llama_sft_s44_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"753525\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\", \"submitted_at\": \"2026-05-20T04:21:19.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 590.1, \"gpu_hours\": 0.16}}, \"llama_sft_s43_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"753922\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\", \"submitted_at\": \"2026-05-20T04:25:41.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 325.6, \"gpu_hours\": 0.09}}}, \"count\": 30, \"total\": 290, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.0863}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c92e819f-c2d5-4feb-ab78-407debe76e2b",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "f1f45492-1fe8-460c-ae4c-f47f88eca11b",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan017_14b_rsft_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-14B + SFT(checkpoint-144) + RSFT\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_14b\\\", \\\"eval_data\\\": \\\"DocRED dev set (985 docs, 12275 gold triples)\\\", \\\"pid\\\": 53413, \\\"gpu\\\": \\\"cuda:0\\\", \\\"gpu_mem_used\\\": \\\"32503 MiB\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"base_model\\\": \\\"/root/autodl-tmp/models/Qwen/Qwen3-14B\\\", \\\"nested_lora\\\": true, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5886, \\\"f1\\\": 0.5886, \\\"format_ok\\\": 985, \\\"format_ok_rate\\\": 1, \\\"truncated\\\": 0, \\\"evi_f1\\\": 0.8392, \\\"edcr\\\": 0.5396}}, \\\"eval_llama_sft_s43_no_evidence_2048_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"58417\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T22:29:47.154Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\\\", \\\"wall_clock_seconds\\\": 15226.5, \\\"gpu_hours\\\": 4.23}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3389, \\\"f1\\\": 0.3575, \\\"format_ok\\\": 834, \\\"format_ok_rate\\\": 0.8467, \\\"truncated\\\": 359, \\\"predictions\\\": 23070, \\\"inference_time_seconds\\\": 14987}}, \\\"eval_llama_sft_s42_with_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\\\", \\\"pid\\\": 55468, \\\"gpu\\\": \\\"cuda:3\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5649, \\\"f1\\\": 0.5767, \\\"format_ok\\\": 976, \\\"format_ok_rate\\\": 0.9909, \\\"truncated\\\": 147, \\\"predictions\\\": 20302, \\\"evi_f1\\\": 0.803, \\\"edcr\\\": 0.6428, \\\"inference_time_seconds\\\": 10491.7}}, \\\"plan017_14b_rsft_no_evidence_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": null, \\\"model_name\\\": \\\"Qwen3-14B + SFT ckpt-144 + RSFT\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_14b/\\\", \\\"eval_data\\\": \\\"docred dev split\\\", \\\"pid\\\": 55039, \\\"gpu\\\": \\\"cuda:2\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5432, \\\"f1\\\": 0.5536, \\\"ign_precision\\\": 0.5193, \\\"ign_recall\\\": 0.5693, \\\"precision\\\": 0.5414, \\\"recall\\\": 0.5664, \\\"evi_f1\\\": 0, \\\"edcr\\\": 0, \\\"format_ok\\\": 953, \\\"format_ok_rate\\\": 0.9675, \\\"n_total\\\": 985, \\\"n_predictions\\\": 15333, \\\"n_truncated\\\": 106, \\\"tp\\\": 6882, \\\"pred_count\\\": 12711, \\\"gold_count\\\": 12151, \\\"inference_time_seconds\\\": 9427.5}}, \\\"eval_llama_sft_s43_no_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"45587\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T18:26:31.570Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 14418.9, \\\"gpu_hours\\\": 4.01}}, \\\"eval_llama_sft_s42_no_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"42346\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T17:41:22.540Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 12923.2, \\\"gpu_hours\\\": 3.59}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.521, \\\"f1\\\": 0.5306, \\\"ign_precision\\\": 0.5342, \\\"ign_recall\\\": 0.5085, \\\"format_ok_rate\\\": 0.8873, \\\"n_format_ok\\\": 874, \\\"n_truncated\\\": 201, \\\"truncation_rate\\\": 0.2041, \\\"n_predictions\\\": 23031, \\\"n_documents\\\": 985, \\\"pred_count_dedup\\\": 11109, \\\"fair_tax_pp\\\": 1.2, \\\"fair_subset_docs\\\": 873, \\\"fair_with_evi_ign_f1\\\": 0.5443, \\\"fair_no_evi_ign_f1\\\": 0.5564, \\\"raw_tax_pp\\\": -1.74, \\\"vs_1024_ign_f1_delta\\\": \\\"-0.09pp\\\", \\\"vs_1024_format_ok_delta\\\": \\\"0pp (874→874)\\\", \\\"vs_1024_fair_tax_delta\\\": \\\"-0.14pp (+1.34→+1.20)\\\"}}, \\\"plan017_14b_rsft_generate_r4\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\\\", \\\"metrics\\\": {\\\"total_lines\\\": 24216, \\\"unique_docs\\\": 3027, \\\"generations_per_doc\\\": 8}}, \\\"metrics\\\": {\\\"total_lines\\\": 24216, \\\"unique_docs\\\": 3027, \\\"generations_per_doc\\\": 8}}, \\\"eval_llama_sft_s43_no_evidence_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"36398\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T16:13:11.226Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\", \\\"wall_clock_seconds\\\": 18025.3, \\\"gpu_hours\\\": 5.01}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3391, \\\"format_compliance\\\": 0.616, \\\"n_truncated\\\": 378}}, \\\"eval_llama_sft_s44_no_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"40255\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T17:07:29.962Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 14763.9, \\\"gpu_hours\\\": 4.1}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.4373, \\\"f1\\\": 0.4504, \\\"ign_precision\\\": 0.3947, \\\"ign_recall\\\": 0.4902, \\\"format_ok_rate\\\": 0.9919, \\\"n_format_ok\\\": 977, \\\"n_truncated\\\": 246, \\\"truncation_rate\\\": 0.2497, \\\"n_predictions\\\": 28366, \\\"n_documents\\\": 985, \\\"fair_tax_pp\\\": -4.18, \\\"fair_subset_docs\\\": 977, \\\"fair_with_evi_ign_f1\\\": 0.4813, \\\"fair_no_evi_ign_f1\\\": 0.4395, \\\"vs_1024_ign_f1_delta\\\": \\\"+10.47pp\\\", \\\"vs_1024_truncation_delta\\\": \\\"-16.7pp\\\"}}, \\\"d112_rsft_s44_ced_score\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 604576, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-base\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44\\\", \\\"output_samples\\\": 3014, \\\"note\\\": \\\"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\\\"}, \\\"metrics\\\": {\\\"total_scored\\\": 24216, \\\"selected_count\\\": 3014, \\\"selection_rate\\\": 0.124, \\\"mean_f1\\\": 0.676, \\\"mean_ced\\\": 0.676}}, \\\"plan017_14b_rsft_train\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"48806\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T19:16:50Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\\\", \\\"data_count\\\": 3015, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_14b\\\", \\\"wall_clock_seconds\\\": 5575.6, \\\"gpu_hours\\\": 1.55}, \\\"metrics\\\": {\\\"train_loss\\\": 0.5005, \\\"mean_token_accuracy\\\": 0.8783, \\\"total_steps\\\": 1131, \\\"runtime_seconds\\\": 3958}}, \\\"d112_rsft_s44_generate\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 584466, \\\"tmux_session\\\": \\\"d112_rsft_s44_generate\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\", \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"top_p\\\": 0.95, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\"}}, \\\"plan017_14b_ced_scoring\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"44419\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T18:10:17.337Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_14b\\\", \\\"wall_clock_seconds\\\": 3793.4, \\\"gpu_hours\\\": 1.05}, \\\"metrics\\\": {\\\"total_scored\\\": 24216, \\\"unique_docs_total\\\": 3027, \\\"selected_count\\\": 3015, \\\"unique_docs_selected\\\": 3015, \\\"selection_rate\\\": 0.1245, \\\"all_mean_f1\\\": 0.616, \\\"all_mean_ced\\\": 0.568, \\\"all_mean_combined\\\": 0.673, \\\"selected_mean_f1\\\": 0.73, \\\"selected_mean_ced\\\": 0.69, \\\"selected_mean_combined\\\": 0.768, \\\"selected_median_f1\\\": 0.75, \\\"selected_median_ced\\\": 0.71, \\\"f1_filter_dropped_gens\\\": 497, \\\"f1_filter_dropped_docs\\\": 12, \\\"truncated_count\\\": 1701, \\\"truncated_ratio\\\": 0.07, \\\"truncated_mean_f1\\\": 0.487, \\\"non_truncated_mean_f1\\\": 0.625, \\\"truncation_f1_gap\\\": 0.139, \\\"format_reward_mean\\\": 0.9996, \\\"output_file\\\": \\\"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\\\", \\\"output_size_mb\\\": 9.1, \\\"runtime_hours\\\": 1}}, \\\"eval_llama_sft_s44_no_evidence\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3326, \\\"f1\\\": 0.3348, \\\"format_compliance\\\": 0.945, \\\"format_ok\\\": 931, \\\"n_documents\\\": 985, \\\"n_truncated\\\": 411}}, \\\"eval_llama_rsft_s44_no_evidence\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\\\", \\\"metrics\\\": {\\\"ign_f1\\\": 0.555, \\\"f1\\\": 0.5674, \\\"edcr\\\": 0.6818, \\\"format_ok\\\": 984, \\\"n_documents\\\": 985, \\\"format_compliance\\\": 0.999, \\\"n_truncated\\\": 178}}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.555, \\\"f1\\\": 0.5674, \\\"evi_f1\\\": 0.001, \\\"evi_f1_joint\\\": 0.0001, \\\"edcr\\\": 0.6818, \\\"format_compliance\\\": 0.999, \\\"n_truncated\\\": 178, \\\"n_predictions\\\": 18089, \\\"inference_time_s\\\": 6555.2, \\\"n_documents\\\": 985, \\\"n_format_ok\\\": 984}}, \\\"eval_llama_sft_s43_no_evidence\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"27322\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T14:08:24.174Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 7282.5, \\\"gpu_hours\\\": 2.02}}, \\\"migration_bjb2_to_westd\\\": {\\\"spec\\\": {\\\"command\\\": \\\"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/\\\", \\\"data_count\\\": 207, \\\"model_name\\\": \\\"N/A\\\", \\\"seed\\\": 0, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/\\\", \\\"log_path\\\": \\\"/tmp/rsync_progress_reporter.sh\\\"}}, \\\"plan017_14b_rsft_generate_r3\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"17644\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:35:24.818Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 13307.5, \\\"gpu_hours\\\": 3.7}}, \\\"eval_llama_sft_s42_no_evidence_std_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"16978\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:31:12.890Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 11295.5, \\\"gpu_hours\\\": 3.14}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5219, \\\"f1\\\": 0.5311, \\\"ign_precision\\\": 0.542, \\\"ign_recall\\\": 0.5031, \\\"evi_f1_joint\\\": 0.0005, \\\"evi_f1_tp\\\": 0.0102, \\\"edcr\\\": 0.58, \\\"format_ok_rate\\\": 0.8873, \\\"n_truncated\\\": 219, \\\"n_predictions\\\": 16292, \\\"inference_time_seconds\\\": 6927.2}}, \\\"llama_sft_s44_train_eval_r3\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"16658\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:30:48.150Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 11252.9, \\\"gpu_hours\\\": 3.13}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.4802, \\\"rel_f1\\\": 0.4902, \\\"evi_f1_joint\\\": 0.3913, \\\"evi_f1_tp\\\": 0.8502, \\\"edcr\\\": 0.6579, \\\"format_ok\\\": \\\"985/985\\\", \\\"n_truncated\\\": 240, \\\"n_predictions\\\": 14990}}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"516711\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:33.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5362.4, \\\"gpu_hours\\\": 1.49}, \\\"metrics\\\": {\\\"train_loss\\\": 0.3862, \\\"mean_token_accuracy\\\": 0.8735, \\\"epochs\\\": 3, \\\"global_steps\\\": 1134, \\\"runtime_seconds\\\": 2894.88, \\\"data_samples\\\": 3018, \\\"ign_f1\\\": 0.5471, \\\"rel_f1\\\": 0.5651, \\\"evi_f1\\\": 0.818, \\\"edcr\\\": 0.6094, \\\"num_preds\\\": 16226, \\\"truncated\\\": \\\"231/985\\\", \\\"format_ok\\\": \\\"985/985\\\"}}, \\\"d102_8b_rsft_k1_s42\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"516605\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:29.717Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5361.8, \\\"gpu_hours\\\": 1.49}, \\\"metrics\\\": {\\\"train_loss\\\": 0.3877, \\\"mean_token_accuracy\\\": 0.8579, \\\"epochs\\\": 3, \\\"global_steps\\\": 1134, \\\"runtime_seconds\\\": 2915.82, \\\"entropy\\\": 0.5847, \\\"data_samples\\\": 3018}}, \\\"llama_sft_s43_train_eval_r3\\\": {\\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_model\\\": \\\"RTX PRO 6000 Blackwell 98GB\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5142, \\\"evi_f1_joint\\\": 0.422, \\\"evi_f1_tp\\\": 0.8245, \\\"edcr\\\": 0.5866, \\\"re_p_ign\\\": 0.4917, \\\"re_r_ign\\\": 0.5389, \\\"train_loss_final\\\": 0.521}}, \\\"plan017_14b_rsft_generate_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"17267\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:31:24.677Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 38.7, \\\"gpu_hours\\\": 0.01}}, \\\"eval_llama_sft_s42_no_evidence_std\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 1000, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"llama_sft_s44_train_eval_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"754497\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:31:57.230Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"wall_clock_seconds\\\": 10893.0, \\\"gpu_hours\\\": 3.03}}, \\\"llama_sft_s43_train_eval_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"754413\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:31:54.309Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"wall_clock_seconds\\\": 10893.3, \\\"gpu_hours\\\": 3.03}}, \\\"plan017_14b_rsft_generate\\\": {\\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\", \\\"cuda:2\\\"], \\\"pid\\\": \\\"712685\\\"}}, \\\"llama_sft_s44_train_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"753525\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:21:19.626Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"N/A - OOM\\\", \\\"wall_clock_seconds\\\": 590.1, \\\"gpu_hours\\\": 0.16}}, \\\"llama_sft_s43_train_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"753922\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:25:41.064Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"N/A - OOM\\\", \\\"wall_clock_seconds\\\": 325.6, \\\"gpu_hours\\\": 0.09}}}, \\\"count\\\": 30, \\\"total\\\": 290, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.0863}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan017_14b_rsft_eval\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-14B + SFT(checkpoint-144) + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 53413, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"32503 MiB\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"base_model\": \"/root/autodl-tmp/models/Qwen/Qwen3-14B\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\", \"log_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\"}, \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.5886, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 0, \"evi_f1\": 0.8392, \"edcr\": 0.5396}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"58417\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\", \"submitted_at\": \"2026-05-20T22:29:47.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\", \"wall_clock_seconds\": 15226.5, \"gpu_hours\": 4.23}, \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987}}, \"eval_llama_sft_s42_with_evidence_2048\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\", \"pid\": 55468, \"gpu\": \"cuda:3\"}, \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}}, \"plan017_14b_rsft_no_evidence_eval\": {\"spec\": {\"command\": \"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": null, \"model_name\": \"Qwen3-14B + SFT ckpt-144 + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b/\", \"eval_data\": \"docred dev split\", \"pid\": 55039, \"gpu\": \"cuda:2\"}, \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}}, \"eval_llama_sft_s43_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"45587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T18:26:31.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14418.9, \"gpu_hours\": 4.01}}, \"eval_llama_sft_s42_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"42346\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:41:22.540Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12923.2, \"gpu_hours\": 3.59}, \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\"}}, \"plan017_14b_rsft_generate_r4\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"36398\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\", \"submitted_at\": \"2026-05-20T16:13:11.226Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\", \"wall_clock_seconds\": 18025.3, \"gpu_hours\": 5.01}, \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}}, \"eval_llama_sft_s44_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"40255\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:07:29.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14763.9, \"gpu_hours\": 4.1}, \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\"}}, \"d112_rsft_s44_ced_score\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}, \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"plan017_14b_rsft_train\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"48806\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\", \"submitted_at\": \"2026-05-20T19:16:50Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"data_count\": 3015, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_14b\", \"wall_clock_seconds\": 5575.6, \"gpu_hours\": 1.55}, \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}}, \"d112_rsft_s44_generate\": {\"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\"}}, \"plan017_14b_ced_scoring\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"44419\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\", \"submitted_at\": \"2026-05-20T18:10:17.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_14b\", \"wall_clock_seconds\": 3793.4, \"gpu_hours\": 1.05}, \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}}, \"eval_llama_sft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\"}, \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}}, \"eval_llama_rsft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"edcr\": 0.6818, \"format_ok\": 984, \"n_documents\": 985, \"format_compliance\": 0.999, \"n_truncated\": 178}}, \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"27322\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\", \"submitted_at\": \"2026-05-20T14:08:24.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7282.5, \"gpu_hours\": 2.02}}, \"migration_bjb2_to_westd\": {\"spec\": {\"command\": \"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/\", \"data_count\": 207, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/\", \"log_path\": \"/tmp/rsync_progress_reporter.sh\"}}, \"plan017_14b_rsft_generate_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17644\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\", \"submitted_at\": \"2026-05-20T11:35:24.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13307.5, \"gpu_hours\": 3.7}}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"16978\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\", \"submitted_at\": \"2026-05-20T11:31:12.890Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11295.5, \"gpu_hours\": 3.14}, \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}}, \"llama_sft_s44_train_eval_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"16658\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\", \"submitted_at\": \"2026-05-20T11:30:48.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11252.9, \"gpu_hours\": 3.13}, \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}}, \"d102_8b_rsft_k1_s43\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu_model\": \"RTX PRO 6000 Blackwell 98GB\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\"}, \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17267\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\", \"submitted_at\": \"2026-05-20T11:31:24.677Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 38.7, \"gpu_hours\": 0.01}}, \"eval_llama_sft_s42_no_evidence_std\": {\"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"llama_sft_s44_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"754497\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:57.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.0, \"gpu_hours\": 3.03}}, \"llama_sft_s43_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"754413\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:54.309Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.3, \"gpu_hours\": 3.03}}, \"plan017_14b_rsft_generate\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"llama_sft_s44_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"753525\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\", \"submitted_at\": \"2026-05-20T04:21:19.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 590.1, \"gpu_hours\": 0.16}}, \"llama_sft_s43_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"753922\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\", \"submitted_at\": \"2026-05-20T04:25:41.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 325.6, \"gpu_hours\": 0.09}}}, \"count\": 30, \"total\": 290, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.0863}}"
    }
  },
  "sourceToolAssistantUUID": "c92e819f-c2d5-4feb-ab78-407debe76e2b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 40_

```json
{
  "type": "last-prompt",
  "leafUuid": "f1f45492-1fe8-460c-ae4c-f47f88eca11b",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Runtime record

_source line 41_

```json
{
  "type": "ai-title",
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Assistant

_source line 42 · 2026-05-21T02:46:32.637Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have:

**Paths confirmed:**
- Base model: `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B`
- SFT adapter (s42): `/root/autodl-tmp/sft_output_llama_3_1_8b` (has `adapter_model.safetensors` at root level, also checkpoint-190, checkpoint-570)
- RSFT adapter (s42, k1): `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1` (has `adapter_model.safetensors` at root, checkpoint-1100, checkpoint-1107)


- GPU is clear on cuda:0

Now I'm constructing the evaluation command using the 14B RSFT eval as a template, setting up the inference script with the model paths, base model, SFT adapter, and data path for the DocRED dataset.

Finishing the command parameters...

For the SFT adapter, I need to figure out whether to use the root-level adapter or a specific checkpoint—the 14B used checkpoint-144, but the LLaMA SFT directory has both root-level adapter files and numbered checkpoints. Let me check what the previous LLaMA evaluation used.

Looking at the SFT evaluation, it pointed directly to the root adapter directory without specifying a checkpoint. But for nested LoRA with RSFT, the structure changes—I'd need to pass the RSFT adapter as the model path, the base model separately, and then the SFT adapter on top.

Checking the RSFT evaluation command, it seems to use relative paths that resolve from the working directory. I should search through the registry more broadly to find if there's an earlier RSFT s42 experiment with evidence that produced that ign_f1=0.5714 result.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f1f45492-1fe8-460c-ae4c-f47f88eca11b",
  "isSidechain": false,
  "requestId": "req_011CbEwyWZtRcaA6dmufcJe3",
  "type": "assistant",
  "uuid": "cd28a9f3-4127-46bd-8c61-51d6cfd3e6aa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSbuxivYKs873RbXRjPW8Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15553,
      "cache_read_input_tokens": 41903,
      "output_tokens": 1025,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15553,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1025,
          "cache_read_input_tokens": 41903,
          "cache_creation_input_tokens": 15553,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15553
          },
          "type": "message"
        }
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

_source line 43 · 2026-05-21T02:46:32.640Z_

找到关键路径了。再搜一下 RSFT s42 的 @1024 eval 记录确认命令模式。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cd28a9f3-4127-46bd-8c61-51d6cfd3e6aa",
  "isSidechain": false,
  "requestId": "req_011CbEwyWZtRcaA6dmufcJe3",
  "type": "assistant",
  "uuid": "1bf9bd48-9b84-4cc6-88a1-4cbdb84ebee0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSbuxivYKs873RbXRjPW8Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15553,
      "cache_read_input_tokens": 41903,
      "output_tokens": 1025,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15553,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1025,
          "cache_read_input_tokens": 41903,
          "cache_creation_input_tokens": 15553,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15553
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-21T02:46:33.216Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01FbE9o2EyhrayY65ebfsxdC`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "spec",
    "metrics"
  ],
  "limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1bf9bd48-9b84-4cc6-88a1-4cbdb84ebee0",
  "isSidechain": false,
  "requestId": "req_011CbEwyWZtRcaA6dmufcJe3",
  "type": "assistant",
  "uuid": "4ddcfdee-4b07-4ad2-aaf7-097ef26c757c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSbuxivYKs873RbXRjPW8Q",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15553,
      "cache_read_input_tokens": 41903,
      "output_tokens": 1025,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 15553,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1025,
          "cache_read_input_tokens": 41903,
          "cache_creation_input_tokens": 15553,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 15553
          },
          "type": "message"
        }
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

_source line 45 · 2026-05-21T02:46:34.181Z_

<details><summary>↩ Tool result · `toolu_01FbE9o2EyhrayY65ebfsxdC`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan017_14b_rsft_eval\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-14B + SFT(checkpoint-144) + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 53413, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"32503 MiB\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"base_model\": \"/root/autodl-tmp/models/Qwen/Qwen3-14B\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\", \"log_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\"}, \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.5886, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 0, \"evi_f1\": 0.8392, \"edcr\": 0.5396}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"58417\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\", \"submitted_at\": \"2026-05-20T22:29:47.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\", \"wall_clock_seconds\": 15226.5, \"gpu_hours\": 4.23}, \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987}}, \"eval_llama_sft_s42_with_evidence_2048\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\", \"pid\": 55468, \"gpu\": \"cuda:3\"}, \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}}, \"plan017_14b_rsft_no_evidence_eval\": {\"spec\": {\"command\": \"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": null, \"model_name\": \"Qwen3-14B + SFT ckpt-144 + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b/\", \"eval_data\": \"docred dev split\", \"pid\": 55039, \"gpu\": \"cuda:2\"}, \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}}, \"eval_llama_sft_s43_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"45587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T18:26:31.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14418.9, \"gpu_hours\": 4.01}}, \"eval_llama_sft_s42_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"42346\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:41:22.540Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12923.2, \"gpu_hours\": 3.59}, \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\"}}, \"plan017_14b_rsft_generate_r4\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"36398\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\", \"submitted_at\": \"2026-05-20T16:13:11.226Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\", \"wall_clock_seconds\": 18025.3, \"gpu_hours\": 5.01}, \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}}, \"eval_llama_sft_s44_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"40255\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:07:29.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14763.9, \"gpu_hours\": 4.1}, \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\"}}, \"d112_rsft_s44_ced_score\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}, \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"plan017_14b_rsft_train\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"48806\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\", \"submitted_at\": \"2026-05-20T19:16:50Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"data_count\": 3015, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_14b\", \"wall_clock_seconds\": 5575.6, \"gpu_hours\": 1.55}, \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}}, \"d112_rsft_s44_generate\": {\"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\"}}, \"plan017_14b_ced_scoring\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"44419\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\", \"submitted_at\": \"2026-05-20T18:10:17.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_14b\", \"wall_clock_seconds\": 3793.4, \"gpu_hours\": 1.05}, \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}}, \"eval_llama_sft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\"}, \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}}, \"eval_llama_rsft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"edcr\": 0.6818, \"format_ok\": 984, \"n_documents\": 985, \"format_compliance\": 0.999, \"n_truncated\": 178}}, \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"27322\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\", \"submitted_at\": \"2026-05-20T14:08:24.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7282.5, \"gpu_hours\": 2.02}}, \"migration_bjb2_to_westd\": {\"spec\": {\"command\": \"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/\", \"data_count\": 207, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/\", \"log_path\": \"/tmp/rsync_progress_reporter.sh\"}}, \"plan017_14b_rsft_generate_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17644\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\", \"submitted_at\": \"2026-05-20T11:35:24.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13307.5, \"gpu_hours\": 3.7}}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"16978\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\", \"submitted_at\": \"2026-05-20T11:31:12.890Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11295.5, \"gpu_hours\": 3.14}, \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}}, \"llama_sft_s44_train_eval_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"16658\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\", \"submitted_at\": \"2026-05-20T11:30:48.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11252.9, \"gpu_hours\": 3.13}, \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}}, \"d102_8b_rsft_k1_s43\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu_model\": \"RTX PRO 6000 Blackwell 98GB\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\"}, \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17267\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\", \"submitted_at\": \"2026-05-20T11:31:24.677Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 38.7, \"gpu_hours\": 0.01}}, \"eval_llama_sft_s42_no_evidence_std\": {\"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"llama_sft_s44_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"754497\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:57.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.0, \"gpu_hours\": 3.03}}, \"llama_sft_s43_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"754413\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:54.309Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.3, \"gpu_hours\": 3.03}}, \"plan017_14b_rsft_generate\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"llama_sft_s44_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"753525\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\", \"submitted_at\": \"2026-05-20T04:21:19.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 590.1, \"gpu_hours\": 0.16}}, \"llama_sft_s43_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"753922\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\", \"submitted_at\": \"2026-05-20T04:25:41.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 325.6, \"gpu_hours\": 0.09}}}, \"count\": 30, \"total\": 290, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9402}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4ddcfdee-4b07-4ad2-aaf7-097ef26c757c",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "9d611c02-8cab-4a4d-950c-96a53e4a6b7b",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan017_14b_rsft_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Qwen3-14B + SFT(checkpoint-144) + RSFT\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_14b\\\", \\\"eval_data\\\": \\\"DocRED dev set (985 docs, 12275 gold triples)\\\", \\\"pid\\\": 53413, \\\"gpu\\\": \\\"cuda:0\\\", \\\"gpu_mem_used\\\": \\\"32503 MiB\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"base_model\\\": \\\"/root/autodl-tmp/models/Qwen/Qwen3-14B\\\", \\\"nested_lora\\\": true, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\\\", \\\"log_path\\\": \\\"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5886, \\\"f1\\\": 0.5886, \\\"format_ok\\\": 985, \\\"format_ok_rate\\\": 1, \\\"truncated\\\": 0, \\\"evi_f1\\\": 0.8392, \\\"edcr\\\": 0.5396}}, \\\"eval_llama_sft_s43_no_evidence_2048_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"58417\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T22:29:47.154Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\\\", \\\"wall_clock_seconds\\\": 15226.5, \\\"gpu_hours\\\": 4.23}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3389, \\\"f1\\\": 0.3575, \\\"format_ok\\\": 834, \\\"format_ok_rate\\\": 0.8467, \\\"truncated\\\": 359, \\\"predictions\\\": 23070, \\\"inference_time_seconds\\\": 14987}}, \\\"eval_llama_sft_s42_with_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\\\", \\\"pid\\\": 55468, \\\"gpu\\\": \\\"cuda:3\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5649, \\\"f1\\\": 0.5767, \\\"format_ok\\\": 976, \\\"format_ok_rate\\\": 0.9909, \\\"truncated\\\": 147, \\\"predictions\\\": 20302, \\\"evi_f1\\\": 0.803, \\\"edcr\\\": 0.6428, \\\"inference_time_seconds\\\": 10491.7}}, \\\"plan017_14b_rsft_no_evidence_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": null, \\\"model_name\\\": \\\"Qwen3-14B + SFT ckpt-144 + RSFT\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_14b/\\\", \\\"eval_data\\\": \\\"docred dev split\\\", \\\"pid\\\": 55039, \\\"gpu\\\": \\\"cuda:2\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5432, \\\"f1\\\": 0.5536, \\\"ign_precision\\\": 0.5193, \\\"ign_recall\\\": 0.5693, \\\"precision\\\": 0.5414, \\\"recall\\\": 0.5664, \\\"evi_f1\\\": 0, \\\"edcr\\\": 0, \\\"format_ok\\\": 953, \\\"format_ok_rate\\\": 0.9675, \\\"n_total\\\": 985, \\\"n_predictions\\\": 15333, \\\"n_truncated\\\": 106, \\\"tp\\\": 6882, \\\"pred_count\\\": 12711, \\\"gold_count\\\": 12151, \\\"inference_time_seconds\\\": 9427.5}}, \\\"eval_llama_sft_s43_no_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"45587\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T18:26:31.570Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 14418.9, \\\"gpu_hours\\\": 4.01}}, \\\"eval_llama_sft_s42_no_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"42346\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T17:41:22.540Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 12923.2, \\\"gpu_hours\\\": 3.59}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.521, \\\"f1\\\": 0.5306, \\\"ign_precision\\\": 0.5342, \\\"ign_recall\\\": 0.5085, \\\"format_ok_rate\\\": 0.8873, \\\"n_format_ok\\\": 874, \\\"n_truncated\\\": 201, \\\"truncation_rate\\\": 0.2041, \\\"n_predictions\\\": 23031, \\\"n_documents\\\": 985, \\\"pred_count_dedup\\\": 11109, \\\"fair_tax_pp\\\": 1.2, \\\"fair_subset_docs\\\": 873, \\\"fair_with_evi_ign_f1\\\": 0.5443, \\\"fair_no_evi_ign_f1\\\": 0.5564, \\\"raw_tax_pp\\\": -1.74, \\\"vs_1024_ign_f1_delta\\\": \\\"-0.09pp\\\", \\\"vs_1024_format_ok_delta\\\": \\\"0pp (874→874)\\\", \\\"vs_1024_fair_tax_delta\\\": \\\"-0.14pp (+1.34→+1.20)\\\"}}, \\\"plan017_14b_rsft_generate_r4\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\\\", \\\"metrics\\\": {\\\"total_lines\\\": 24216, \\\"unique_docs\\\": 3027, \\\"generations_per_doc\\\": 8}}, \\\"metrics\\\": {\\\"total_lines\\\": 24216, \\\"unique_docs\\\": 3027, \\\"generations_per_doc\\\": 8}}, \\\"eval_llama_sft_s43_no_evidence_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"36398\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T16:13:11.226Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\", \\\"wall_clock_seconds\\\": 18025.3, \\\"gpu_hours\\\": 5.01}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3391, \\\"format_compliance\\\": 0.616, \\\"n_truncated\\\": 378}}, \\\"eval_llama_sft_s44_no_evidence_2048\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"40255\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T17:07:29.962Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 14763.9, \\\"gpu_hours\\\": 4.1}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.4373, \\\"f1\\\": 0.4504, \\\"ign_precision\\\": 0.3947, \\\"ign_recall\\\": 0.4902, \\\"format_ok_rate\\\": 0.9919, \\\"n_format_ok\\\": 977, \\\"n_truncated\\\": 246, \\\"truncation_rate\\\": 0.2497, \\\"n_predictions\\\": 28366, \\\"n_documents\\\": 985, \\\"fair_tax_pp\\\": -4.18, \\\"fair_subset_docs\\\": 977, \\\"fair_with_evi_ign_f1\\\": 0.4813, \\\"fair_no_evi_ign_f1\\\": 0.4395, \\\"vs_1024_ign_f1_delta\\\": \\\"+10.47pp\\\", \\\"vs_1024_truncation_delta\\\": \\\"-16.7pp\\\"}}, \\\"d112_rsft_s44_ced_score\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"pid\\\": 604576, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/\\\", \\\"data_count\\\": 24216, \\\"model_name\\\": \\\"cross-encoder/nli-deberta-v3-base\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44/\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_4b_sft_s44\\\", \\\"output_samples\\\": 3014, \\\"note\\\": \\\"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\\\"}, \\\"metrics\\\": {\\\"total_scored\\\": 24216, \\\"selected_count\\\": 3014, \\\"selection_rate\\\": 0.124, \\\"mean_f1\\\": 0.676, \\\"mean_ced\\\": 0.676}}, \\\"plan017_14b_rsft_train\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"48806\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T19:16:50Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\\\", \\\"data_count\\\": 3015, \\\"model_name\\\": \\\"Qwen3-14B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b/checkpoint-144\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_14b\\\", \\\"wall_clock_seconds\\\": 5575.6, \\\"gpu_hours\\\": 1.55}, \\\"metrics\\\": {\\\"train_loss\\\": 0.5005, \\\"mean_token_accuracy\\\": 0.8783, \\\"total_steps\\\": 1131, \\\"runtime_seconds\\\": 3958}}, \\\"d112_rsft_s44_generate\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_ids\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-4B\\\", \\\"seed\\\": 42, \\\"pid\\\": 584466, \\\"tmux_session\\\": \\\"d112_rsft_s44_generate\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_seed44\\\", \\\"output_dir\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\", \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"top_p\\\": 0.95, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_4b_sft_s44\\\"}}, \\\"plan017_14b_ced_scoring\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"44419\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T18:10:17.337Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_scored_14b\\\", \\\"wall_clock_seconds\\\": 3793.4, \\\"gpu_hours\\\": 1.05}, \\\"metrics\\\": {\\\"total_scored\\\": 24216, \\\"unique_docs_total\\\": 3027, \\\"selected_count\\\": 3015, \\\"unique_docs_selected\\\": 3015, \\\"selection_rate\\\": 0.1245, \\\"all_mean_f1\\\": 0.616, \\\"all_mean_ced\\\": 0.568, \\\"all_mean_combined\\\": 0.673, \\\"selected_mean_f1\\\": 0.73, \\\"selected_mean_ced\\\": 0.69, \\\"selected_mean_combined\\\": 0.768, \\\"selected_median_f1\\\": 0.75, \\\"selected_median_ced\\\": 0.71, \\\"f1_filter_dropped_gens\\\": 497, \\\"f1_filter_dropped_docs\\\": 12, \\\"truncated_count\\\": 1701, \\\"truncated_ratio\\\": 0.07, \\\"truncated_mean_f1\\\": 0.487, \\\"non_truncated_mean_f1\\\": 0.625, \\\"truncation_f1_gap\\\": 0.139, \\\"format_reward_mean\\\": 0.9996, \\\"output_file\\\": \\\"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\\\", \\\"output_size_mb\\\": 9.1, \\\"runtime_hours\\\": 1}}, \\\"eval_llama_sft_s44_no_evidence\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.3326, \\\"f1\\\": 0.3348, \\\"format_compliance\\\": 0.945, \\\"format_ok\\\": 931, \\\"n_documents\\\": 985, \\\"n_truncated\\\": 411}}, \\\"eval_llama_rsft_s44_no_evidence\\\": {\\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\\\", \\\"metrics\\\": {\\\"ign_f1\\\": 0.555, \\\"f1\\\": 0.5674, \\\"edcr\\\": 0.6818, \\\"format_ok\\\": 984, \\\"n_documents\\\": 985, \\\"format_compliance\\\": 0.999, \\\"n_truncated\\\": 178}}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.555, \\\"f1\\\": 0.5674, \\\"evi_f1\\\": 0.001, \\\"evi_f1_joint\\\": 0.0001, \\\"edcr\\\": 0.6818, \\\"format_compliance\\\": 0.999, \\\"n_truncated\\\": 178, \\\"n_predictions\\\": 18089, \\\"inference_time_s\\\": 6555.2, \\\"n_documents\\\": 985, \\\"n_format_ok\\\": 984}}, \\\"eval_llama_sft_s43_no_evidence\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"27322\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T14:08:24.174Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 7282.5, \\\"gpu_hours\\\": 2.02}}, \\\"migration_bjb2_to_westd\\\": {\\\"spec\\\": {\\\"command\\\": \\\"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/\\\", \\\"data_count\\\": 207, \\\"model_name\\\": \\\"N/A\\\", \\\"seed\\\": 0, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/\\\", \\\"log_path\\\": \\\"/tmp/rsync_progress_reporter.sh\\\"}}, \\\"plan017_14b_rsft_generate_r3\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"17644\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:35:24.818Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 13307.5, \\\"gpu_hours\\\": 3.7}}, \\\"eval_llama_sft_s42_no_evidence_std_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"16978\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:31:12.890Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 11295.5, \\\"gpu_hours\\\": 3.14}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5219, \\\"f1\\\": 0.5311, \\\"ign_precision\\\": 0.542, \\\"ign_recall\\\": 0.5031, \\\"evi_f1_joint\\\": 0.0005, \\\"evi_f1_tp\\\": 0.0102, \\\"edcr\\\": 0.58, \\\"format_ok_rate\\\": 0.8873, \\\"n_truncated\\\": 219, \\\"n_predictions\\\": 16292, \\\"inference_time_seconds\\\": 6927.2}}, \\\"llama_sft_s44_train_eval_r3\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"16658\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:30:48.150Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 11252.9, \\\"gpu_hours\\\": 3.13}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.4802, \\\"rel_f1\\\": 0.4902, \\\"evi_f1_joint\\\": 0.3913, \\\"evi_f1_tp\\\": 0.8502, \\\"edcr\\\": 0.6579, \\\"format_ok\\\": \\\"985/985\\\", \\\"n_truncated\\\": 240, \\\"n_predictions\\\": 14990}}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"516711\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:33.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 43, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5362.4, \\\"gpu_hours\\\": 1.49}, \\\"metrics\\\": {\\\"train_loss\\\": 0.3862, \\\"mean_token_accuracy\\\": 0.8735, \\\"epochs\\\": 3, \\\"global_steps\\\": 1134, \\\"runtime_seconds\\\": 2894.88, \\\"data_samples\\\": 3018, \\\"ign_f1\\\": 0.5471, \\\"rel_f1\\\": 0.5651, \\\"evi_f1\\\": 0.818, \\\"edcr\\\": 0.6094, \\\"num_preds\\\": 16226, \\\"truncated\\\": \\\"231/985\\\", \\\"format_ok\\\": \\\"985/985\\\"}}, \\\"d102_8b_rsft_k1_s42\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"516605\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\\\", \\\"submitted_at\\\": \\\"2026-05-18T07:22:29.717Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"data_path\\\": \\\"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\\\", \\\"data_count\\\": 3018, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\\\", \\\"wall_clock_seconds\\\": 5361.8, \\\"gpu_hours\\\": 1.49}, \\\"metrics\\\": {\\\"train_loss\\\": 0.3877, \\\"mean_token_accuracy\\\": 0.8579, \\\"epochs\\\": 3, \\\"global_steps\\\": 1134, \\\"runtime_seconds\\\": 2915.82, \\\"entropy\\\": 0.5847, \\\"data_samples\\\": 3018}}, \\\"llama_sft_s43_train_eval_r3\\\": {\\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu_model\\\": \\\"RTX PRO 6000 Blackwell 98GB\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\\\"}, \\\"metrics\\\": {\\\"ign_f1\\\": 0.5142, \\\"evi_f1_joint\\\": 0.422, \\\"evi_f1_tp\\\": 0.8245, \\\"edcr\\\": 0.5866, \\\"re_p_ign\\\": 0.4917, \\\"re_r_ign\\\": 0.5389, \\\"train_loss_final\\\": 0.521}}, \\\"plan017_14b_rsft_generate_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"17267\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T11:31:24.677Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 38.7, \\\"gpu_hours\\\": 0.01}}, \\\"eval_llama_sft_s42_no_evidence_std\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 1000, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\"}}, \\\"llama_sft_s44_train_eval_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"754497\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:31:57.230Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"wall_clock_seconds\\\": 10893.0, \\\"gpu_hours\\\": 3.03}}, \\\"llama_sft_s43_train_eval_r2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"754413\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:31:54.309Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"wall_clock_seconds\\\": 10893.3, \\\"gpu_hours\\\": 3.03}}, \\\"plan017_14b_rsft_generate\\\": {\\\"spec\\\": {\\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/train_annotated.json\\\", \\\"data_count\\\": 3027, \\\"model_name\\\": \\\"Qwen3-14B + SFT adapter\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/sft_output_14b\\\", \\\"eval_data\\\": \\\"docred-train_annotated (N=8 generation)\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/rsft_generations_14b\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\\\\\"\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:0\\\", \\\"cuda:2\\\"], \\\"pid\\\": \\\"712685\\\"}}, \\\"llama_sft_s44_train_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"753525\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:21:19.626Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 44, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"N/A - OOM\\\", \\\"wall_clock_seconds\\\": 590.1, \\\"gpu_hours\\\": 0.16}}, \\\"llama_sft_s43_train_eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"753922\\\", \\\"log_path\\\": \\\"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-20T04:25:41.064Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred\\\", \\\"data_count\\\": 3053, \\\"model_name\\\": \\\"meta-llama/Meta-Llama-3.1-8B\\\", \\\"seed\\\": 43, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"eval_data\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"checkpoint_path\\\": \\\"N/A - OOM\\\", \\\"wall_clock_seconds\\\": 325.6, \\\"gpu_hours\\\": 0.09}}}, \\\"count\\\": 30, \\\"total\\\": 290, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9402}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan017_14b_rsft_eval\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_14b --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval --batch_size 1 --max_new_tokens 1024 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-14B + SFT(checkpoint-144) + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 53413, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"32503 MiB\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"base_model\": \"/root/autodl-tmp/models/Qwen/Qwen3-14B\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval/\", \"log_path\": \"/root/autodl-tmp/freige/eval_outputs/plan017_14b_rsft_eval.log\"}, \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.5886, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 0, \"evi_f1\": 0.8392, \"edcr\": 0.5396}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"58417\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048_r2.log\", \"submitted_at\": \"2026-05-20T22:29:47.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048/\", \"wall_clock_seconds\": 15226.5, \"gpu_hours\": 4.23}, \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987}}, \"eval_llama_sft_s42_with_evidence_2048\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_sft_s42_with_evidence_2048.log\", \"pid\": 55468, \"gpu\": \"cuda:3\"}, \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}}, \"plan017_14b_rsft_no_evidence_eval\": {\"spec\": {\"command\": \"bash scripts/plan017/step4b_eval_14b_rsft_no_evidence.sh\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": null, \"model_name\": \"Qwen3-14B + SFT ckpt-144 + RSFT\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_14b/\", \"eval_data\": \"docred dev split\", \"pid\": 55039, \"gpu\": \"cuda:2\"}, \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}}, \"eval_llama_sft_s43_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"45587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T18:26:31.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14418.9, \"gpu_hours\": 4.01}}, \"eval_llama_sft_s42_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"42346\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:41:22.540Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12923.2, \"gpu_hours\": 3.59}, \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\"}}, \"plan017_14b_rsft_generate_r4\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model Qwen3-14B --sft_adapter checkpoint-144 --resume\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b/generations.jsonl\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r4.log\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"36398\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence_r2.log\", \"submitted_at\": \"2026-05-20T16:13:11.226Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence_r2\", \"wall_clock_seconds\": 18025.3, \"gpu_hours\": 5.01}, \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}}, \"eval_llama_sft_s44_no_evidence_2048\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s44 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 2048 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence_2048\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"40255\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence_2048.log\", \"submitted_at\": \"2026-05-20T17:07:29.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14763.9, \"gpu_hours\": 4.1}, \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\"}}, \"d112_rsft_s44_ced_score\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && export HF_HUB_OFFLINE=1 && export TRANSFORMERS_OFFLINE=1 && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && bash scripts/d112/step2_ced_score.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 604576, \"data_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/\", \"data_count\": 24216, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_source\": \"d112_rsft_s44_gen (4 shards, SFT s44 N=8 generation)\", \"eval_data\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44/ (3027 docs x 8 candidates)\", \"output_dir\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44/\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_ced_score.log\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_4b_sft_s44\", \"output_samples\": 3014, \"note\": \"CED scoring completed successfully. 24216 candidates scored, 3014 samples selected (k=1). Cron misdiagnosed as failed due to no W&B/sentinel.\"}, \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"plan017_14b_rsft_train\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --rsft_data_path /root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_14b --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft-14b-plan017\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"48806\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_train.log\", \"submitted_at\": \"2026-05-20T19:16:50Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"data_count\": 3015, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b/checkpoint-144\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_14b\", \"wall_clock_seconds\": 5575.6, \"gpu_hours\": 1.55}, \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}}, \"d112_rsft_s44_generate\": {\"spec\": {\"command\": \"python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output_seed44 --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_4b_sft_s44 --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"pid\": 584466, \"tmux_session\": \"d112_rsft_s44_generate\", \"log_path\": \"/root/runs/faith-evidence-ie/d112_rsft_s44_generate.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output_seed44\", \"eval_data\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_seed44\", \"output_dir\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\", \"num_generations\": 8, \"temperature\": 0.7, \"top_p\": 0.95, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_4b_sft_s44\"}}, \"plan017_14b_ced_scoring\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/plan017/step2_ced_score_14b.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"44419\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_ced_scoring.log\", \"submitted_at\": \"2026-05-20T18:10:17.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_scored_14b\", \"wall_clock_seconds\": 3793.4, \"gpu_hours\": 1.05}, \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}}, \"eval_llama_sft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path sft_output_llama_3_1_8b_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_sft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s44_no_evidence.log\"}, \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}}, \"eval_llama_rsft_s44_no_evidence\": {\"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path rsft_output_llama_3_1_8b_k1_s44 --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1_s44\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s44_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_rsft_s44_no_evidence.log\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"edcr\": 0.6818, \"format_ok\": 984, \"n_documents\": 985, \"format_compliance\": 0.999, \"n_truncated\": 178}}, \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b_s43 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s43_no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"27322\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s43_no_evidence.log\", \"submitted_at\": \"2026-05-20T14:08:24.174Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7282.5, \"gpu_hours\": 2.02}}, \"migration_bjb2_to_westd\": {\"spec\": {\"command\": \"rsync -avz -e 'ssh -i /tmp/migration_key -p 12179' root@connect.bjb2.seetacloud.com:/root/autodl-tmp/ /root/autodl-tmp/\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/\", \"data_count\": 207, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/\", \"log_path\": \"/tmp/rsync_progress_reporter.sh\"}}, \"plan017_14b_rsft_generate_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b/checkpoint-144 --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17644\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r3.log\", \"submitted_at\": \"2026-05-20T11:35:24.818Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13307.5, \"gpu_hours\": 3.7}}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=3 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output_llama_3_1_8b --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --no-quantize --no_evidence --output_dir /root/autodl-tmp/eval_results/eval_llama_sft_s42_no_evidence_std\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"16978\", \"log_path\": \"~/runs/faith-evidence-ie/eval_llama_sft_s42_no_evidence_std_r2.log\", \"submitted_at\": \"2026-05-20T11:31:12.890Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11295.5, \"gpu_hours\": 3.14}, \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}}, \"llama_sft_s44_train_eval_r3\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=2 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"16658\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r3.log\", \"submitted_at\": \"2026-05-20T11:30:48.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11252.9, \"gpu_hours\": 3.13}, \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}}, \"d102_8b_rsft_k1_s43\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 43 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s43_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"516711\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s43.log\", \"submitted_at\": \"2026-05-18T07:22:33.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 43, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1_s43/checkpoint-1134\", \"wall_clock_seconds\": 5362.4, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --sft_adapter /root/autodl-tmp/sft_output_qwen3_8b_bf16 --rsft_data_path /root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_qwen3_8b_k1 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 8 --warmup_steps 100 --save_steps 50 --save_total_limit 2 --max_length 2048 --seed 42 --lora_rank 64 --lora_alpha 128 --bf16 --wandb_project freige-rsft --wandb_run_name rsft_qwen3_8b_k1_s42_resume --resume_from_checkpoint /root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-250\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"516605\", \"log_path\": \"~/runs/faith-evidence-ie/d102_8b_rsft_k1_s42.log\", \"submitted_at\": \"2026-05-18T07:22:29.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/rsft_scored_qwen3_8b_k1/rsft_train.jsonl\", \"data_count\": 3018, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_qwen3_8b_k1/checkpoint-1134\", \"wall_clock_seconds\": 5361.8, \"gpu_hours\": 1.49}, \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu_model\": \"RTX PRO 6000 Blackwell 98GB\", \"checkpoint_path\": \"/root/autodl-tmp/sft_output_llama_3_1_8b_s43/\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r3.log\"}, \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"17267\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate_r2.log\", \"submitted_at\": \"2026-05-20T11:31:24.677Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 38.7, \"gpu_hours\": 0.01}}, \"eval_llama_sft_s42_no_evidence_std\": {\"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output_llama_3_1_8b --no_evidence\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}}, \"llama_sft_s44_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=3 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"754497\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:57.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.0, \"gpu_hours\": 3.03}}, \"llama_sft_s43_train_eval_r2\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=1 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"754413\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval_r2.log\", \"submitted_at\": \"2026-05-20T04:31:54.309Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 10893.3, \"gpu_hours\": 3.03}}, \"plan017_14b_rsft_generate\": {\"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-14B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output_14b\", \"eval_data\": \"docred-train_annotated (N=8 generation)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations_14b\", \"log_path\": \"~/runs/faith-evidence-ie/plan017_14b_rsft_generate.log\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen/Qwen3-14B --sft_adapter /root/autodl-tmp/sft_output_14b --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations_14b --num_generations 8 --temperature 0.7 --top_p 0.95 --batch_size 1 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:2\"], \"pid\": \"712685\"}}, \"llama_sft_s44_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s44_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"753525\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s44_train_eval.log\", \"submitted_at\": \"2026-05-20T04:21:19.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 590.1, \"gpu_hours\": 0.16}}, \"llama_sft_s43_train_eval\": {\"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && GPU=0 bash scripts/seed_expansion/llama_sft_s43_train_eval.sh'\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"753922\", \"log_path\": \"~/runs/faith-evidence-ie/llama_sft_s43_train_eval.log\", \"submitted_at\": \"2026-05-20T04:25:41.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"meta-llama/Meta-Llama-3.1-8B\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"checkpoint_path\": \"N/A - OOM\", \"wall_clock_seconds\": 325.6, \"gpu_hours\": 0.09}}}, \"count\": 30, \"total\": 290, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9402}}"
    }
  },
  "sourceToolAssistantUUID": "4ddcfdee-4b07-4ad2-aaf7-097ef26c757c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 46_

```json
{
  "type": "last-prompt",
  "leafUuid": "9d611c02-8cab-4a4d-950c-96a53e4a6b7b",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Runtime record

_source line 47_

```json
{
  "type": "ai-title",
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Assistant

_source line 48 · 2026-05-21T02:46:56.007Z_

<details><summary>Logged reasoning block</summary>

```text
I didn't find the LLaMA RSFT s42 @1024 eval in the recent 30 results. Let me check with a different search or look at the eval command from the inference module to understand the exact arguments. Actually let me also check what the existing eval output directories look like and check for the `--sft_adapter` argument usage in the inference code.

Key info gathered:
- **Base model**: `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B`
- **SFT adapter (s42)**: `/root/autodl-tmp/sft_output_llama_3_1_8b` (final adapter at root)


- **RSFT adapter (s42, k1)**: `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1` (final adapter at root)
- **GPU**: cuda:0 = 0 MiB ✅

Now I can see the pattern for the 14B RSFT eval — it uses the RSFT adapter as the main model path, the base model separately, and chains in the SFT adapter as well.

For the LLaMA RSFT s42 with-evidence setup, I should follow the same nested LoRA structure: point to the RSFT adapter output, specify the base model, and layer the SFT adapter on top. I'm verifying that the command includes evidence (no `--no_evidence` flag), which is correct. I'm considering whether to wrap this in bash with conda activation like some other commands do, but since the 14B RSFT eval worked fine with just the direct Python call, I'll follow that pattern for consistency. Now I need to load the job submission and registry tools to proceed.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9d611c02-8cab-4a4d-950c-96a53e4a6b7b",
  "isSidechain": false,
  "requestId": "req_011CbEx14fTSBSMnKZnDR6Se",
  "type": "assistant",
  "uuid": "6047267d-2790-4628-9f5a-7f687e172f0a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVhJGTRSCCLTUjoRoAgzvx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14799,
      "cache_read_input_tokens": 57456,
      "output_tokens": 1147,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14799,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1147,
          "cache_read_input_tokens": 57456,
          "cache_creation_input_tokens": 14799,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14799
          },
          "type": "message"
        }
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

_source line 49 · 2026-05-21T02:46:56.009Z_

所有路径确认。现在加载提交工具。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6047267d-2790-4628-9f5a-7f687e172f0a",
  "isSidechain": false,
  "requestId": "req_011CbEx14fTSBSMnKZnDR6Se",
  "type": "assistant",
  "uuid": "c80b8135-a912-4bab-8777-f0a6bd1fe816",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVhJGTRSCCLTUjoRoAgzvx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14799,
      "cache_read_input_tokens": 57456,
      "output_tokens": 1147,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14799,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1147,
          "cache_read_input_tokens": 57456,
          "cache_creation_input_tokens": 14799,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14799
          },
          "type": "message"
        }
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

_source line 50 · 2026-05-21T02:46:56.162Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_017wT5yZYdP9gg2tk7Qz8bdZ`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__register_artifact",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c80b8135-a912-4bab-8777-f0a6bd1fe816",
  "isSidechain": false,
  "requestId": "req_011CbEx14fTSBSMnKZnDR6Se",
  "type": "assistant",
  "uuid": "0c997fd4-da37-4296-91ec-da8d68205f10",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVhJGTRSCCLTUjoRoAgzvx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14799,
      "cache_read_input_tokens": 57456,
      "output_tokens": 1147,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14799,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1147,
          "cache_read_input_tokens": 57456,
          "cache_creation_input_tokens": 14799,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14799
          },
          "type": "message"
        }
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

_source line 51 · 2026-05-21T02:46:56.167Z_

<details><summary>↩ Tool result · `toolu_017wT5yZYdP9gg2tk7Qz8bdZ`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_execute"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__update_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0c997fd4-da37-4296-91ec-da8d68205f10",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "1a2d32a0-6652-473c-b1e4-6f555dc46d5f",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 26
  },
  "sourceToolAssistantUUID": "0c997fd4-da37-4296-91ec-da8d68205f10",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 52 · 2026-05-21T02:47:05.540Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have everything I need. Let me construct the eval command and submit it.

Key parameters:
- Base model: `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B`
- SFT adapter: `/root/autodl-tmp/sft_output_llama_3_1_8b`
- RSFT adapter: `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1`
- GPU: cuda:0 (0 MiB, clear) ✅ C001
- CUDA_VISIBLE_DEVICES=0 ✅ C002


- With-evidence mode enabled ✅ C005
- max_new_tokens: 2048, batch_size: 1, seed: 42
- split: dev, no quantization
- output_dir: /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048

I'm building the command following the same pattern as the 14B RSFT eval, wrapping it in bash with conda activation, then submitting the job and registering it simultaneously.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1a2d32a0-6652-473c-b1e4-6f555dc46d5f",
  "isSidechain": false,
  "requestId": "req_011CbEx2gfSQBAvEe9jdXQSV",
  "type": "assistant",
  "uuid": "86aa1973-8517-409d-bc0b-0288bf1addc1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017s2LqDz8oeJ4g7ENZ9QQf8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2484,
      "cache_read_input_tokens": 72255,
      "output_tokens": 752,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 752,
          "cache_read_input_tokens": 72255,
          "cache_creation_input_tokens": 2484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2484
          },
          "type": "message"
        }
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

_source line 53 · 2026-05-21T02:47:05.543Z_

cuda:0 空闲 (0 MiB) ✅。提交 eval。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "86aa1973-8517-409d-bc0b-0288bf1addc1",
  "isSidechain": false,
  "requestId": "req_011CbEx2gfSQBAvEe9jdXQSV",
  "type": "assistant",
  "uuid": "f4dd0f22-5be2-4935-adc7-d1f79effa288",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017s2LqDz8oeJ4g7ENZ9QQf8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2484,
      "cache_read_input_tokens": 72255,
      "output_tokens": 752,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 752,
          "cache_read_input_tokens": 72255,
          "cache_creation_input_tokens": 2484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2484
          },
          "type": "message"
        }
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

_source line 54 · 2026-05-21T02:47:07.162Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_01RAwTwBE3Yumj12hnRbwunt`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 nohup python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42 > /root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log 2>&1 & echo PID=\\$!\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f4dd0f22-5be2-4935-adc7-d1f79effa288",
  "isSidechain": false,
  "requestId": "req_011CbEx2gfSQBAvEe9jdXQSV",
  "type": "assistant",
  "uuid": "d8ce2728-61ab-4157-ae54-b51dddf35d59",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017s2LqDz8oeJ4g7ENZ9QQf8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2484,
      "cache_read_input_tokens": 72255,
      "output_tokens": 752,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2484,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 752,
          "cache_read_input_tokens": 72255,
          "cache_creation_input_tokens": 2484,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2484
          },
          "type": "message"
        }
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

_source line 55 · 2026-05-21T02:47:37.632Z_

<details><summary>↩ Tool result · `toolu_01RAwTwBE3Yumj12hnRbwunt`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"PID=70706\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 30.42}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d8ce2728-61ab-4157-ae54-b51dddf35d59",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "b4072741-0925-4a31-a390-7c9c3e4a42bc",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"PID=70706\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 30.42}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"PID=70706\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 30.42}}"
    }
  },
  "sourceToolAssistantUUID": "d8ce2728-61ab-4157-ae54-b51dddf35d59",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 56 · 2026-05-21T02:47:37.645Z_

```json
{
  "parentUuid": "b4072741-0925-4a31-a390-7c9c3e4a42bc",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "948ae806-8150-4a49-bb44-f47b26c19937",
  "timestamp": "2026-05-21T02:47:37.645Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 57 · 2026-05-21T02:47:41.838Z_

<details><summary>Logged reasoning block</summary>

```text
PID=70706. Now let me verify it's running and check GPU usage, then register in registry.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "948ae806-8150-4a49-bb44-f47b26c19937",
  "isSidechain": false,
  "requestId": "req_011CbEx5jywwbbSJUVgG5Kmu",
  "type": "assistant",
  "uuid": "7ff35e8c-bce8-43ce-9a74-e759e78050b9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gpe85CxVhEijV157UUH9bW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 936,
      "cache_read_input_tokens": 74739,
      "output_tokens": 407,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 936,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 407,
          "cache_read_input_tokens": 74739,
          "cache_creation_input_tokens": 936,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 936
          },
          "type": "message"
        }
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

_source line 58 · 2026-05-21T02:47:42.332Z_

PID=70706。验证启动和 GPU 占用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7ff35e8c-bce8-43ce-9a74-e759e78050b9",
  "isSidechain": false,
  "requestId": "req_011CbEx5jywwbbSJUVgG5Kmu",
  "type": "assistant",
  "uuid": "8ab251bc-bdd4-4164-ba59-8870bbcbe989",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gpe85CxVhEijV157UUH9bW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 936,
      "cache_read_input_tokens": 74739,
      "output_tokens": 407,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 936,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 407,
          "cache_read_input_tokens": 74739,
          "cache_creation_input_tokens": 936,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 936
          },
          "type": "message"
        }
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

_source line 59 · 2026-05-21T02:47:43.279Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_014BnJgoVdttE2PvDPNyTHwK`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ps -p 70706 -o pid,cmd --no-headers",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ab251bc-bdd4-4164-ba59-8870bbcbe989",
  "isSidechain": false,
  "requestId": "req_011CbEx5jywwbbSJUVgG5Kmu",
  "type": "assistant",
  "uuid": "153d71c9-da01-48cd-b387-9c2c182bb1e9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gpe85CxVhEijV157UUH9bW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 936,
      "cache_read_input_tokens": 74739,
      "output_tokens": 407,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 936,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 407,
          "cache_read_input_tokens": 74739,
          "cache_creation_input_tokens": 936,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 936
          },
          "type": "message"
        }
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

_source line 60 · 2026-05-21T02:47:43.759Z_

<details><summary>↩ Tool result · `toolu_014BnJgoVdttE2PvDPNyTHwK`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \" 70706 bash -c source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 nohup python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42 > /root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log 2>&1 & echo PID=$!\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "153d71c9-da01-48cd-b387-9c2c182bb1e9",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "26acdeab-2340-4059-b3b0-c3e4cbcb10b9",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\" 70706 bash -c source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 nohup python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42 > /root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log 2>&1 & echo PID=$!\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.45}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \" 70706 bash -c source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 nohup python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42 > /root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log 2>&1 & echo PID=$!\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"
    }
  },
  "sourceToolAssistantUUID": "153d71c9-da01-48cd-b387-9c2c182bb1e9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 61 · 2026-05-21T02:47:44.229Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Gwt3xUHZbtdSHtKyRTzKt1`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "nvidia-smi --query-gpu=index,memory.used,memory.total --format=csv,noheader",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "26acdeab-2340-4059-b3b0-c3e4cbcb10b9",
  "isSidechain": false,
  "requestId": "req_011CbEx5jywwbbSJUVgG5Kmu",
  "type": "assistant",
  "uuid": "f0844016-7c57-4ea9-ba8d-8e4528dbdfe2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gpe85CxVhEijV157UUH9bW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 936,
      "cache_read_input_tokens": 74739,
      "output_tokens": 407,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 936,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 407,
          "cache_read_input_tokens": 74739,
          "cache_creation_input_tokens": 936,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 936
          },
          "type": "message"
        }
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

_source line 62 · 2026-05-21T02:47:44.787Z_

<details><summary>↩ Tool result · `toolu_01Gwt3xUHZbtdSHtKyRTzKt1`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"0, 18879 MiB, 97887 MiB\\n1, 32503 MiB, 97887 MiB\\n2, 18879 MiB, 97887 MiB\\n3, 18879 MiB, 97887 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.55}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f0844016-7c57-4ea9-ba8d-8e4528dbdfe2",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "57115435-6c1f-4999-b318-7c11797dd70a",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"0, 18879 MiB, 97887 MiB\\\\n1, 32503 MiB, 97887 MiB\\\\n2, 18879 MiB, 97887 MiB\\\\n3, 18879 MiB, 97887 MiB\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.55}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"0, 18879 MiB, 97887 MiB\\n1, 32503 MiB, 97887 MiB\\n2, 18879 MiB, 97887 MiB\\n3, 18879 MiB, 97887 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.55}}"
    }
  },
  "sourceToolAssistantUUID": "f0844016-7c57-4ea9-ba8d-8e4528dbdfe2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 63 · 2026-05-21T02:47:44.807Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_014Ahg4nx3qLwbPXQ3E5L8KQ`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "tail -5 /root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "57115435-6c1f-4999-b318-7c11797dd70a",
  "isSidechain": false,
  "requestId": "req_011CbEx5jywwbbSJUVgG5Kmu",
  "type": "assistant",
  "uuid": "7bdb4a55-3cdc-4dc9-a3f0-5e3701d61a34",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gpe85CxVhEijV157UUH9bW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 936,
      "cache_read_input_tokens": 74739,
      "output_tokens": 407,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 936,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 407,
          "cache_read_input_tokens": 74739,
          "cache_creation_input_tokens": 936,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 936
          },
          "type": "message"
        }
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

_source line 64 · 2026-05-21T02:47:45.331Z_

<details><summary>↩ Tool result · `toolu_014Ahg4nx3qLwbPXQ3E5L8KQ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"2026-05-21 10:47:17,959 INFO Loaded 998 documents from /root/autodl-tmp/data/docred/dev.json\\n2026-05-21 10:47:18,149 INFO Processed 12275 relation samples from 998 documents (5445 samples without hard negatives)\\n2026-05-21 10:47:18,261 INFO Prepared 985 eval documents, 12275 gold triples\\n\\rInference:   0%|          | 0/985 [00:00<?, ?it/s][transformers] Ignoring clean_up_tokenization_spaces=True for BPE tokenizer TokenizersBackend. The clean_up_tokenization post-processing step is designed for WordPiece tokenizers and is destructive for BPE (it strips spaces before punctuation). Set clean_up_tokenization_spaces=False to suppress this warning, or set clean_up_tokenization_spaces_for_bpe_even_though_it_will_corrupt_output=True to force cleanup anyway.\\n\\rInference:   0%|          | 1/985 [00:03<1:00:57,  3.72s/it]\\rInference:   0%|          | 2/985 [00:18<2:43:40,  9.99s/it]\\rInference:   0%|          | 3/985 [00:26<2:29:51,  9.16s/it]\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.51}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7bdb4a55-3cdc-4dc9-a3f0-5e3701d61a34",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "efc2a2d9-31d2-42bb-990a-20d203ee9dec",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"2026-05-21 10:47:17,959 INFO Loaded 998 documents from /root/autodl-tmp/data/docred/dev.json\\\\n2026-05-21 10:47:18,149 INFO Processed 12275 relation samples from 998 documents (5445 samples without hard negatives)\\\\n2026-05-21 10:47:18,261 INFO Prepared 985 eval documents, 12275 gold triples\\\\n\\\\rInference:   0%|          | 0/985 [00:00<?, ?it/s][transformers] Ignoring clean_up_tokenization_spaces=True for BPE tokenizer TokenizersBackend. The clean_up_tokenization post-processing step is designed for WordPiece tokenizers and is destructive for BPE (it strips spaces before punctuation). Set clean_up_tokenization_spaces=False to suppress this warning, or set clean_up_tokenization_spaces_for_bpe_even_though_it_will_corrupt_output=True to force cleanup anyway.\\\\n\\\\rInference:   0%|          | 1/985 [00:03<1:00:57,  3.72s/it]\\\\rInference:   0%|          | 2/985 [00:18<2:43:40,  9.99s/it]\\\\rInference:   0%|          | 3/985 [00:26<2:29:51,  9.16s/it]\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.51}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"2026-05-21 10:47:17,959 INFO Loaded 998 documents from /root/autodl-tmp/data/docred/dev.json\\n2026-05-21 10:47:18,149 INFO Processed 12275 relation samples from 998 documents (5445 samples without hard negatives)\\n2026-05-21 10:47:18,261 INFO Prepared 985 eval documents, 12275 gold triples\\n\\rInference:   0%|          | 0/985 [00:00<?, ?it/s][transformers] Ignoring clean_up_tokenization_spaces=True for BPE tokenizer TokenizersBackend. The clean_up_tokenization post-processing step is designed for WordPiece tokenizers and is destructive for BPE (it strips spaces before punctuation). Set clean_up_tokenization_spaces=False to suppress this warning, or set clean_up_tokenization_spaces_for_bpe_even_though_it_will_corrupt_output=True to force cleanup anyway.\\n\\rInference:   0%|          | 1/985 [00:03<1:00:57,  3.72s/it]\\rInference:   0%|          | 2/985 [00:18<2:43:40,  9.99s/it]\\rInference:   0%|          | 3/985 [00:26<2:29:51,  9.16s/it]\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.51}}"
    }
  },
  "sourceToolAssistantUUID": "7bdb4a55-3cdc-4dc9-a3f0-5e3701d61a34",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 65_

```json
{
  "type": "last-prompt",
  "leafUuid": "efc2a2d9-31d2-42bb-990a-20d203ee9dec",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Runtime record

_source line 66_

```json
{
  "type": "ai-title",
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Assistant

_source line 67 · 2026-05-21T02:47:49.407Z_

进程运行中，cuda:0 占用 18879 MiB，推理已开始（985 docs）。注册 registry。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "efc2a2d9-31d2-42bb-990a-20d203ee9dec",
  "isSidechain": false,
  "requestId": "req_011CbEx6JubfL2ufsnUk4VFM",
  "type": "assistant",
  "uuid": "6d8039fb-600e-49c4-a960-f6c72972f2bd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WiqxELpea2J1S9XUeJJKPs",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1464,
      "cache_read_input_tokens": 75675,
      "output_tokens": 719,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 719,
          "cache_read_input_tokens": 75675,
          "cache_creation_input_tokens": 1464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1464
          },
          "type": "message"
        }
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

_source line 68 · 2026-05-21T02:47:55.276Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01XP4QvREQooiPXyjh4PCqa5`</summary>

```json
{
  "exp_id": "eval_llama_rsft_s42_with_evidence_2048",
  "field": "status",
  "value": "RUNNING",
  "project": "faith-evidence-ie",
  "spec": {
    "command": "CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42",
    "server": "rtx5090-4x",
    "data_path": "/root/autodl-tmp/data/docred/dev.json",
    "data_count": 985,
    "model_name": "Meta-Llama-3.1-8B + SFT + RSFT(k1)",
    "seed": 42,
    "checkpoint_source": "/root/autodl-tmp/rsft_output_llama_3_1_8b_k1",
    "eval_data": "DocRED dev set (985 docs, 12275 gold triples)",
    "pid": 70706,
    "gpu": "cuda:0",
    "gpu_mem_used": "18879 MiB",
    "base_model": "/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B",
    "sft_adapter": "/root/autodl-tmp/sft_output_llama_3_1_8b",
    "nested_lora": true,
    "checkpoint_path": "/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048",
    "log_path": "/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log"
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6d8039fb-600e-49c4-a960-f6c72972f2bd",
  "isSidechain": false,
  "requestId": "req_011CbEx6JubfL2ufsnUk4VFM",
  "type": "assistant",
  "uuid": "317ea8a4-9c33-4e80-90a1-7c21c5f7320f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WiqxELpea2J1S9XUeJJKPs",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1464,
      "cache_read_input_tokens": 75675,
      "output_tokens": 719,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1464,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 719,
          "cache_read_input_tokens": 75675,
          "cache_creation_input_tokens": 1464,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1464
          },
          "type": "message"
        }
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

_source line 69 · 2026-05-21T02:47:56.470Z_

<details><summary>↩ Tool result · `toolu_01XP4QvREQooiPXyjh4PCqa5`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"Invalid transition: PREPARING → RUNNING. Allowed: ['PENDING', 'QUEUED']\", \"metadata\": {\"elapsed_seconds\": 1.0981}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "317ea8a4-9c33-4e80-90a1-7c21c5f7320f",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "8ac6c9e4-118a-4288-80c7-7013446a3eaf",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"Invalid transition: PREPARING → RUNNING. Allowed: ['PENDING', 'QUEUED']\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.0981}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"Invalid transition: PREPARING → RUNNING. Allowed: ['PENDING', 'QUEUED']\", \"metadata\": {\"elapsed_seconds\": 1.0981}}"
    }
  },
  "sourceToolAssistantUUID": "317ea8a4-9c33-4e80-90a1-7c21c5f7320f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 70 · 2026-05-21T02:47:59.720Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_016dCqhE8nwcvfBhn5ehyzDy`</summary>

```json
{
  "exp_id": "eval_llama_rsft_s42_with_evidence_2048",
  "field": "status",
  "value": "QUEUED",
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ac6c9e4-118a-4288-80c7-7013446a3eaf",
  "isSidechain": false,
  "requestId": "req_011CbEx78r9BvpyoozCkvLuZ",
  "type": "assistant",
  "uuid": "db522b10-a13a-4518-ab6a-b067fccecea3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01D7kWgk3KNJpAqkfxFgxwf9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 760,
      "cache_read_input_tokens": 77139,
      "output_tokens": 137,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 760,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 137,
          "cache_read_input_tokens": 77139,
          "cache_creation_input_tokens": 760,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 760
          },
          "type": "message"
        }
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

_source line 71 · 2026-05-21T02:48:03.519Z_

<details><summary>↩ Tool result · `toolu_016dCqhE8nwcvfBhn5ehyzDy`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_s42_with_evidence_2048\", \"experiment\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:48:01.287Z\", \"updated_at\": \"2026-05-21T02:48:01.287Z\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 3.7773}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "db522b10-a13a-4518-ab6a-b067fccecea3",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "d181754f-fd7b-4064-bd0b-3a7957007b1d",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_s42_with_evidence_2048\\\", \\\"experiment\\\": {\\\"status\\\": \\\"QUEUED\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-21T02:48:01.287Z\\\", \\\"updated_at\\\": \\\"2026-05-21T02:48:01.287Z\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 3.7773}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_s42_with_evidence_2048\", \"experiment\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:48:01.287Z\", \"updated_at\": \"2026-05-21T02:48:01.287Z\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 3.7773}}"
    }
  },
  "sourceToolAssistantUUID": "db522b10-a13a-4518-ab6a-b067fccecea3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 72 · 2026-05-21T02:48:10.684Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01MTfUUZxyPptmMPijEqqW9o`</summary>

```json
{
  "exp_id": "eval_llama_rsft_s42_with_evidence_2048",
  "field": "status",
  "value": "RUNNING",
  "project": "faith-evidence-ie",
  "spec": {
    "command": "CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42",
    "server": "rtx5090-4x",
    "data_path": "/root/autodl-tmp/data/docred/dev.json",
    "data_count": 985,
    "model_name": "Meta-Llama-3.1-8B + SFT + RSFT(k1)",
    "seed": 42,
    "checkpoint_source": "/root/autodl-tmp/rsft_output_llama_3_1_8b_k1",
    "eval_data": "DocRED dev set (985 docs, 12275 gold triples)",
    "pid": 70706,
    "gpu": "cuda:0",
    "gpu_mem_used": "18879 MiB",
    "base_model": "/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B",
    "sft_adapter": "/root/autodl-tmp/sft_output_llama_3_1_8b",
    "nested_lora": true,
    "checkpoint_path": "/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048",
    "log_path": "/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log"
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d181754f-fd7b-4064-bd0b-3a7957007b1d",
  "isSidechain": false,
  "requestId": "req_011CbEx7eboL2WEzCJ8hK7Gs",
  "type": "assistant",
  "uuid": "9457750d-f3dc-44eb-b096-f5a0696ae33a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0196Vskb6SdUSN1NiXBGUFEy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 287,
      "cache_read_input_tokens": 77899,
      "output_tokens": 832,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 287,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 832,
          "cache_read_input_tokens": 77899,
          "cache_creation_input_tokens": 287,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 287
          },
          "type": "message"
        }
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

_source line 73 · 2026-05-21T02:48:13.699Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01WE6xwy1HCYaC2uGyNn7ZWA`</summary>

```json
{
  "exp_id": "eval_llama_rsft_s42_with_evidence_2048",
  "field": "hypothesis",
  "value": "matched@2048 control: LLaMA RSFT s42 with-evi@2048。@1024 ign_f1=0.5714。预期 delta<1pp，验证 RSFT evidence tax 在 matched budget 下稳定。",
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9457750d-f3dc-44eb-b096-f5a0696ae33a",
  "isSidechain": false,
  "requestId": "req_011CbEx7eboL2WEzCJ8hK7Gs",
  "type": "assistant",
  "uuid": "55cc6e99-7f0d-46ad-88fb-1d146e18456b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0196Vskb6SdUSN1NiXBGUFEy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 287,
      "cache_read_input_tokens": 77899,
      "output_tokens": 832,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 287,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 832,
          "cache_read_input_tokens": 77899,
          "cache_creation_input_tokens": 287,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 287
          },
          "type": "message"
        }
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

_source line 74 · 2026-05-21T02:48:13.798Z_

<details><summary>↩ Tool result · `toolu_01MTfUUZxyPptmMPijEqqW9o`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_s42_with_evidence_2048\", \"experiment\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:48:01.287Z\", \"updated_at\": \"2026-05-21T02:48:11.699Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT(k1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 70706, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"18879 MiB\", \"base_model\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log\"}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 3.1006}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9457750d-f3dc-44eb-b096-f5a0696ae33a",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "f45218cc-5b71-43d0-b055-2516d5a23c23",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_s42_with_evidence_2048\\\", \\\"experiment\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-21T02:48:01.287Z\\\", \\\"updated_at\\\": \\\"2026-05-21T02:48:11.699Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B + SFT + RSFT(k1)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\\\", \\\"eval_data\\\": \\\"DocRED dev set (985 docs, 12275 gold triples)\\\", \\\"pid\\\": 70706, \\\"gpu\\\": \\\"cuda:0\\\", \\\"gpu_mem_used\\\": \\\"18879 MiB\\\", \\\"base_model\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"nested_lora\\\": true, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log\\\"}}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 3.1006}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_s42_with_evidence_2048\", \"experiment\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:48:01.287Z\", \"updated_at\": \"2026-05-21T02:48:11.699Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT(k1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 70706, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"18879 MiB\", \"base_model\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log\"}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 3.1006}}"
    }
  },
  "sourceToolAssistantUUID": "9457750d-f3dc-44eb-b096-f5a0696ae33a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 75 · 2026-05-21T02:48:15.465Z_

<details><summary>↩ Tool result · `toolu_01WE6xwy1HCYaC2uGyNn7ZWA`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_s42_with_evidence_2048\", \"experiment\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:48:01.287Z\", \"updated_at\": \"2026-05-21T02:48:14.804Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT(k1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 70706, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"18879 MiB\", \"base_model\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log\"}, \"hypothesis\": \"matched@2048 control: LLaMA RSFT s42 with-evi@2048。@1024 ign_f1=0.5714。预期 delta<1pp，验证 RSFT evidence tax 在 matched budget 下稳定。\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.6544}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "55cc6e99-7f0d-46ad-88fb-1d146e18456b",
  "isSidechain": false,
  "promptId": "ffa82c09-cd0b-4983-9623-435280a971f4",
  "type": "user",
  "uuid": "b46f041a-5e64-4818-9a69-c7b7498d96fd",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"eval_llama_rsft_s42_with_evidence_2048\\\", \\\"experiment\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-21T02:48:01.287Z\\\", \\\"updated_at\\\": \\\"2026-05-21T02:48:14.804Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42\\\", \\\"server\\\": \\\"rtx5090-4x\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\", \\\"data_count\\\": 985, \\\"model_name\\\": \\\"Meta-Llama-3.1-8B + SFT + RSFT(k1)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\\\", \\\"eval_data\\\": \\\"DocRED dev set (985 docs, 12275 gold triples)\\\", \\\"pid\\\": 70706, \\\"gpu\\\": \\\"cuda:0\\\", \\\"gpu_mem_used\\\": \\\"18879 MiB\\\", \\\"base_model\\\": \\\"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\\\", \\\"sft_adapter\\\": \\\"/root/autodl-tmp/sft_output_llama_3_1_8b\\\", \\\"nested_lora\\\": true, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048\\\", \\\"log_path\\\": \\\"/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log\\\"}, \\\"hypothesis\\\": \\\"matched@2048 control: LLaMA RSFT s42 with-evi@2048。@1024 ign_f1=0.5714。预期 delta<1pp，验证 RSFT evidence tax 在 matched budget 下稳定。\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.6544}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"eval_llama_rsft_s42_with_evidence_2048\", \"experiment\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:48:01.287Z\", \"updated_at\": \"2026-05-21T02:48:14.804Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b --data_path /root/autodl-tmp/data/docred --split dev --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Meta-Llama-3.1-8B + SFT + RSFT(k1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_llama_3_1_8b_k1\", \"eval_data\": \"DocRED dev set (985 docs, 12275 gold triples)\", \"pid\": 70706, \"gpu\": \"cuda:0\", \"gpu_mem_used\": \"18879 MiB\", \"base_model\": \"/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output_llama_3_1_8b\", \"nested_lora\": true, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048\", \"log_path\": \"/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log\"}, \"hypothesis\": \"matched@2048 control: LLaMA RSFT s42 with-evi@2048。@1024 ign_f1=0.5714。预期 delta<1pp，验证 RSFT evidence tax 在 matched budget 下稳定。\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.6544}}"
    }
  },
  "sourceToolAssistantUUID": "55cc6e99-7f0d-46ad-88fb-1d146e18456b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 76 · 2026-05-21T02:48:24.569Z_

已启动。

| 项目 | 值 |
|------|-----|
| **exp_id** | `eval_llama_rsft_s42_with_evidence_2048` |
| **PID** | 70706 |
| **GPU** | cuda:0, 18879 MiB |
| **Base** | `/root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B` |
| **SFT adapter** | `/root/autodl-tmp/sft_output_llama_3_1_8b` |
| **RSFT adapter** | `/root/autodl-tmp/rsft_output_llama_3_1_8b_k1` |
| **Output** | `/root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048` |
| **Log** | `/root/runs/faith-evidence-ie/eval_llama_rsft_s42_with_evidence_2048.log` |

**完整命令：**
```
CUDA_VISIBLE_DEVICES=0 python -m freige.eval.inference \
  --model_path /root/autodl-tmp/rsft_output_llama_3_1_8b_k1 \
  --base_model /root/autodl-tmp/models/meta-llama/Meta-Llama-3.1-8B \
  --sft_adapter /root/autodl-tmp/sft_output_llama_3_1_8b \
  --data_path /root/autodl-tmp/data/docred --split dev \
  --output_dir /root/autodl-tmp/eval_results/eval_llama_rsft_s42_with_evidence_2048 \
  --batch_size 1 --max_new_tokens 2048 --no-quantize --seed 42
```

推理已进行中（~9s/it, 预计 ~2.5h）。Nested LoRA: base → merge SFT → load RSFT。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b46f041a-5e64-4818-9a69-c7b7498d96fd",
  "isSidechain": false,
  "requestId": "req_011CbEx8Xh6vaTa3CKrDvXz8",
  "type": "assistant",
  "uuid": "49b785ae-73d8-4c4c-961d-ac37c7d8e0f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L9DT9C9f3wTqDYuhJ5iWVp",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2331,
      "cache_read_input_tokens": 78186,
      "output_tokens": 522,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2331,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 522,
          "cache_read_input_tokens": 78186,
          "cache_creation_input_tokens": 2331,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2331
          },
          "type": "message"
        }
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

_source line 77_

```json
{
  "type": "last-prompt",
  "leafUuid": "49b785ae-73d8-4c4c-961d-ac37c7d8e0f1",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

### Runtime record

_source line 78_

```json
{
  "type": "ai-title",
  "aiTitle": "LLaMA RSFT s42 with-evidence 2048 eval",
  "sessionId": "7c9d941b-0177-4185-b3c0-aef43b48d2e1"
}
```

---

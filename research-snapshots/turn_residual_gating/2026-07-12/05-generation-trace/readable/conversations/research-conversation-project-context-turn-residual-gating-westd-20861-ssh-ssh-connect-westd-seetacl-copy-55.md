# Research conversation: <project_context> # 项目: turn_residual_gating ## 运行环境 - 服务器名: westd-20861 - SSH 连接命令: ssh connect.westd.seetacloud.com # 

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 62
- **Recorded user turns:** 1
- **Tool calls:** 16
- **Original source:** `logs/chats/exported-trajectories/account-1/1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3.jsonl`
- **Structured JSON:** [`02655a766e959f685123.json`](../../sessions/02/02655a766e959f685123.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-22T04:54:19.509Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-22T04:54:19.509Z",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "content": "&lt;project_context>\n# 项目: turn_residual_gating\n\n## 运行环境\n- 服务器名: westd-20861\n- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/turn_residual_gating\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n## 任务：experiment_plan.yaml 与 registry 同步\n\n### 目标\n更新 experiment_plan.yaml 中的 plan_id → registry_id 映射，使 compute_coverage_matrix 输出准确。\n\n### 步骤\n\n1. 读取当前 experiment_plan.yaml：\n   `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml`\n\n2. 更新以下映射（添加或修改 registry_id 字段）：\n\n**C5 跨模型（plan_009-012）**：\n- plan_009 → registry_id: llama_phase1_gar_diag\n- plan_010 → registry_id: llama_tg_s42\n- plan_011 → registry_id: llama_lora_only_s42\n- plan_012 → 需要关联多个 eval：llama_eval_s42, llama_ar_matched_eval（如果 registry_id 只能是一个，用主要的那个；如果支持多个，全部列出）\n\n**C7 Multi-seed（plan_019）**：\n- plan_019 → 需要关联：v7_tg_s123, v8b_ss_s123, eval_v7_tg_s123, eval_v8b_ss_s123（如果只能单个 registry_id，用 v7_tg_s123 作为主实验）\n\n**W8（plan_023）**：\n- plan_023 已有 registry_id: phase2_tg_s42_v8b_ss_fixed\n- 额外关联 phase2_tg_s42_v8b_resume（实际成功的版本）\n\n**其他需要修复的**：\n- plan_015 和 plan_017 如果是 orphaned 状态，检查是否需要更新\n\n3. 编辑文件（用 Edit 工具，不是重写整个文件）\n\n4. 验证：调用 `compute_coverage_matrix` 确认输出合理\n\n### 注意\n- 保持 YAML 格式正确\n- 不要修改除 registry_id 之外的字段\n- 如果 plan 条目不存在，不要创建新条目\n"
}
```

---

### Runtime record

_source line 2 · 2026-05-22T04:54:19.513Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-22T04:54:19.513Z",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

## Round 1

60 recorded events

### User

_source line 3 · 2026-05-22T04:54:19.552Z_

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
## 任务：experiment_plan.yaml 与 registry 同步

### 目标
更新 experiment_plan.yaml 中的 plan_id → registry_id 映射，使 compute_coverage_matrix 输出准确。

### 步骤

1. 读取当前 experiment_plan.yaml：
   `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml`

2. 更新以下映射（添加或修改 registry_id 字段）：

**C5 跨模型（plan_009-012）**：
- plan_009 → registry_id: llama_phase1_gar_diag
- plan_010 → registry_id: llama_tg_s42
- plan_011 → registry_id: llama_lora_only_s42
- plan_012 → 需要关联多个 eval：llama_eval_s42, llama_ar_matched_eval（如果 registry_id 只能是一个，用主要的那个；如果支持多个，全部列出）

**C7 Multi-seed（plan_019）**：
- plan_019 → 需要关联：v7_tg_s123, v8b_ss_s123, eval_v7_tg_s123, eval_v8b_ss_s123（如果只能单个 registry_id，用 v7_tg_s123 作为主实验）

**W8（plan_023）**：
- plan_023 已有 registry_id: phase2_tg_s42_v8b_ss_fixed
- 额外关联 phase2_tg_s42_v8b_resume（实际成功的版本）

**其他需要修复的**：
- plan_015 和 plan_017 如果是 orphaned 状态，检查是否需要更新

3. 编辑文件（用 Edit 工具，不是重写整个文件）

4. 验证：调用 `compute_coverage_matrix` 确认输出合理

### 注意
- 保持 YAML 格式正确
- 不要修改除 registry_id 之外的字段
- 如果 plan 条目不存在，不要创建新条目


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "a9656f53-c79f-4e2f-b761-23d32b8305a5",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-22T04:54:19.551Z_

```json
{
  "parentUuid": "a9656f53-c79f-4e2f-b761-23d32b8305a5",
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
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
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
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "c7fa8940-7548-42e9-8eef-0d4355181f25",
  "timestamp": "2026-05-22T04:54:19.551Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 5 · 2026-05-22T04:54:19.551Z_

```json
{
  "parentUuid": "c7fa8940-7548-42e9-8eef-0d4355181f25",
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
  "uuid": "ff0c8b14-4ece-4d10-a5d0-61026b3d7ace",
  "timestamp": "2026-05-22T04:54:19.551Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Runtime record

_source line 6 · 2026-05-22T04:54:19.551Z_

```json
{
  "parentUuid": "ff0c8b14-4ece-4d10-a5d0-61026b3d7ace",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "e6737906-a49a-4778-9aaa-b18ce5d078fc",
  "timestamp": "2026-05-22T04:54:19.551Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
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
  "aiTitle": "Sync experiment_plan.yaml with registry mappings",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Assistant

_source line 8 · 2026-05-22T04:54:26.456Z_

Let me start by reading the current experiment_plan.yaml and registry.yaml to understand the structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6737906-a49a-4778-9aaa-b18ce5d078fc",
  "isSidechain": false,
  "requestId": "req_011CbH1Z2fefiXGvvYJRiSfu",
  "type": "assistant",
  "uuid": "1095f212-2d8f-4887-906a-b80daa6d9b26",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NuqZZsfLKKbihSjCs1sQ7X",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12964,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 178,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12964,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12964
          },
          "type": "message"
        }
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

_source line 9 · 2026-05-22T04:54:27.280Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LHu1LATnBi5ZzK7r1yYHQb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1095f212-2d8f-4887-906a-b80daa6d9b26",
  "isSidechain": false,
  "requestId": "req_011CbH1Z2fefiXGvvYJRiSfu",
  "type": "assistant",
  "uuid": "ae471087-9b53-42e3-a14f-927fed59c30b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NuqZZsfLKKbihSjCs1sQ7X",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12964,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 178,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12964,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12964
          },
          "type": "message"
        }
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

_source line 10 · 2026-05-22T04:54:27.293Z_

<details><summary>↩ Tool result · `toolu_01LHu1LATnBi5ZzK7r1yYHQb`</summary>

```text
1	experiments:
2	- id: plan_001
3	  claim: C1
4	  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)
5	  priority: P0
6	  gpu_budget_hours: 2
7	  deps: []
8	  registry_id: phase1_gar_diag
9	  status: done
10	- id: plan_002
11	  claim: C2
12	  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference
13	    GAR 0.016
14	  priority: P0
15	  gpu_budget_hours: 6
16	  deps:
17	  - plan_001
18	  registry_id: phase2_tg_s42_v7
19	  status: done
20	- id: plan_003
21	  claim: C4
22	  description: Uniform Gate ablation - isolate turn conditioning contribution
23	  priority: P0
24	  gpu_budget_hours: 6
25	  deps:
26	  - plan_001
27	  registry_id: phase2_ug_s42
28	  status: done
29	- id: plan_004
30	  claim: C4
31	  description: LoRA-only ablation - isolate gating mechanism contribution
32	  priority: P0
33	  gpu_budget_hours: 6
34	  deps:
35	  - plan_001
36	  registry_id: phase2_lora_only_s42
37	  status: done
38	- id: plan_005
39	  claim: C4
40	  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)
41	  priority: P0
42	  gpu_budget_hours: 2
43	  deps:
44	  - plan_002
45	  - plan_003
46	  - plan_004
47	  registry_id: phase2_4way_eval
48	  status: done
49	- id: plan_006
50	  claim: C3
51	  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR
52	    gradient cos_sim + magnitude ratio
53	  priority: P0
54	  gpu_budget_hours: 0.5
55	  deps:
56	  - plan_002
57	  registry_id: analysis_gradient_conflict
58	  status: done
59	- id: plan_007
60	  claim: C3
61	  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)
62	  priority: P0
63	  gpu_budget_hours: 0.5
64	  deps:
65	  - plan_002
66	  - plan_003
67	  - plan_004
68	  registry_id: analysis_attention_heatmap
69	  status: done
70	- id: plan_008
71	  claim: C2, C4
72	  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000
73	    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'
74	  priority: P0
75	  gpu_budget_hours: 2
76	  deps:
77	  - plan_005
78	  status: planned
79	  registry_id: phase2_4way_eval_heldout
80	- id: plan_009
81	  claim: C5
82	  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay
83	    exists on different architecture
84	  priority: P0
85	  gpu_budget_hours: 0.5
86	  deps: []
87	  status: planned
88	- id: plan_010
89	  claim: C5
90	  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama
91	  priority: P0
92	  gpu_budget_hours: 7
93	  deps:
94	  - plan_009
95	  status: planned
96	- id: plan_011
97	  claim: C5
98	  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation
99	    (D020)
100	  priority: P0
101	  gpu_budget_hours: 7
102	  deps:
103	  - plan_009
104	  status: planned
105	  registry_id: llama_lora_only_s42
106	- id: plan_012
107	  claim: C5
108	  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out
109	    data
110	  priority: P0
111	  gpu_budget_hours: 1
112	  deps:
113	  - plan_010
114	  - plan_011
115	  status: planned
116	- id: plan_013
117	  claim: C3
118	  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition
119	    is model-agnostic
120	  priority: P1
121	  gpu_budget_hours: 0.5
122	  deps:
123	  - plan_010
124	  status: planned
125	- id: plan_014
126	  claim: W3
127	  description: Downstream task sanity check - simple instruction retention test across
128	    turns to link GAR to task performance
129	  priority: P2
130	  gpu_budget_hours: 1
131	  deps:
132	  - plan_005
133	  status: planned
134	- id: plan_015
135	  claim: C4, W7
136	  description: Statistical significance analysis - paired bootstrap CI from held-out
137	    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically
138	    supports 'zero benefit'. Addresses Dream W3 (single seed).
139	  priority: P1
140	  gpu_budget_hours: 0.5
141	  deps:
142	  - plan_008
143	  status: done
144	  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212
145	  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],
146	    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero
147	    benefit. W7 addressed.'
148	- id: plan_016
149	  claim: W8
150	  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled
151	    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).
152	    Test whether closing exposure bias gap narrows the 30x training-inference GAR
153	    gap. Constructive direction that upgrades paper from pure negative result.
154	  priority: P1
155	  gpu_budget_hours: 8
156	  deps:
157	  - plan_008
158	  status: planned
159	  registry_id: phase2_tg_s42_v8_schedsampling
160	- id: plan_017
161	  claim: R4
162	  description: Code-paper architecture verification - confirm ThreadGate implementation
163	    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code
164	    audit, no GPU.
165	  priority: P0
166	  gpu_budget_hours: 0
167	  deps: []
168	  status: done
169	  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058
170	  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote
171	    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'
172	- id: plan_018
173	  claim: C3, W8
174	  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for
175	    gate params only. If 30x gap persists after removing gradient conflict → causal
176	    evidence that exposure bias (not gradient competition) is the root cause.
177	  priority: P0
178	  gpu_budget_hours: 8
179	  deps:
180	  - plan_006
181	  registry_id: phase2_tg_s42_v9_pcgrad
182	  status: done
183	- id: plan_019
184	  claim: C2, MF5
185	  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.
186	    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.
187	  priority: P1
188	  gpu_budget_hours: 6
189	  deps:
190	  - plan_002
191	  status: planned
192	- id: plan_020
193	  claim: C4, MF6
194	  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000
195	    from UltraChat). Boost bootstrap CI statistical power.
196	  priority: P1
197	  gpu_budget_hours: 2
198	  deps:
199	  - plan_008
200	  status: planned
201	- id: plan_022
202	  claim: C3, SF4
203	  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient
204	    competition trend under higher GAR weight. If budget allows, add λ=0.1.
205	  priority: P2
206	  gpu_budget_hours: 2
207	  deps:
208	  - plan_002
209	  status: planned
210	- id: plan_023
211	  claim: W8, C3
212	  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option
213	    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0
214	    (match v7). Tests whether training on model-generated text closes the 30x distribution
215	    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial
216	    remedy''. D026.'
217	  priority: P1
218	  gpu_budget_hours: 8
219	  deps:
220	  - plan_002
221	  status: planned
222	  registry_id: phase2_tg_s42_v8b_ss_fixed
223	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ae471087-9b53-42e3-a14f-927fed59c30b",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "3231bf26-6237-4bee-ab6d-abd5bcf187d4",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
      "content": "experiments:\n- id: plan_001\n  claim: C1\n  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: phase1_gar_diag\n  status: done\n- id: plan_002\n  claim: C2\n  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference\n    GAR 0.016\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_tg_s42_v7\n  status: done\n- id: plan_003\n  claim: C4\n  description: Uniform Gate ablation - isolate turn conditioning contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_ug_s42\n  status: done\n- id: plan_004\n  claim: C4\n  description: LoRA-only ablation - isolate gating mechanism contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_lora_only_s42\n  status: done\n- id: plan_005\n  claim: C4\n  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: phase2_4way_eval\n  status: done\n- id: plan_006\n  claim: C3\n  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR\n    gradient cos_sim + magnitude ratio\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  registry_id: analysis_gradient_conflict\n  status: done\n- id: plan_007\n  claim: C3\n  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: analysis_attention_heatmap\n  status: done\n- id: plan_008\n  claim: C2, C4\n  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000\n    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_005\n  status: planned\n  registry_id: phase2_4way_eval_heldout\n- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_ss_fixed\n",
      "numLines": 223,
      "startLine": 1,
      "totalLines": 223
    }
  },
  "sourceToolAssistantUUID": "ae471087-9b53-42e3-a14f-927fed59c30b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-22T04:54:27.316Z_

<details open><summary>🔧 Tool call — Read · `toolu_01V8rT9NpXeNutch9NcfDHgv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/registry.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3231bf26-6237-4bee-ab6d-abd5bcf187d4",
  "isSidechain": false,
  "requestId": "req_011CbH1Z2fefiXGvvYJRiSfu",
  "type": "assistant",
  "uuid": "e1331fee-fdd0-4cf6-898e-07ad2b3e1790",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NuqZZsfLKKbihSjCs1sQ7X",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12964,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 178,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 12964,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12964
          },
          "type": "message"
        }
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

_source line 12 · 2026-05-22T04:54:27.613Z_

<details><summary>↩ Tool result · reported error · `toolu_01V8rT9NpXeNutch9NcfDHgv`</summary>

```text
File content (29673 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e1331fee-fdd0-4cf6-898e-07ad2b3e1790",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "2ba0275b-a3a4-4c0b-92b0-7b1d6bda7c54",
  "toolUseResult": "Error: File content (29673 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "e1331fee-fdd0-4cf6-898e-07ad2b3e1790",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 13 · 2026-05-22T04:54:31.102Z_

<details><summary>Logged reasoning block</summary>

```text
The registry.yaml is too large to read at once. Let me grep for the specific registry IDs I need to verify.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2ba0275b-a3a4-4c0b-92b0-7b1d6bda7c54",
  "isSidechain": false,
  "requestId": "req_011CbH1ZcxAYdrKDbao6eziy",
  "type": "assistant",
  "uuid": "69b32238-f47b-497d-bccb-54bb1e94b0be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017BUSYk9nkr4asMmz8LpyHF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3105,
      "cache_read_input_tokens": 24805,
      "output_tokens": 301,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3105,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 301,
          "cache_read_input_tokens": 24805,
          "cache_creation_input_tokens": 3105,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3105
          },
          "type": "message"
        }
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

_source line 14 · 2026-05-22T04:54:31.409Z_

Let me search the registry for the specific IDs mentioned in the task.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "69b32238-f47b-497d-bccb-54bb1e94b0be",
  "isSidechain": false,
  "requestId": "req_011CbH1ZcxAYdrKDbao6eziy",
  "type": "assistant",
  "uuid": "191d7669-6d0c-4513-a6d9-4aa35a6041d0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017BUSYk9nkr4asMmz8LpyHF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3105,
      "cache_read_input_tokens": 24805,
      "output_tokens": 301,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3105,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 301,
          "cache_read_input_tokens": 24805,
          "cache_creation_input_tokens": 3105,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3105
          },
          "type": "message"
        }
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

_source line 15 · 2026-05-22T04:54:35.669Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01FwB8YDxdxeZsNNW5usKF6F`</summary>

```json
{
  "pattern": "^- id: (llama_phase1_gar_diag|llama_tg_s42|llama_lora_only_s42|llama_eval_s42|llama_ar_matched_eval|v7_tg_s123|v8b_ss_s123|eval_v7_tg_s123|eval_v8b_ss_s123|phase2_tg_s42_v8b_ss_fixed|phase2_tg_s42_v8b_resume)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/registry.yaml",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "191d7669-6d0c-4513-a6d9-4aa35a6041d0",
  "isSidechain": false,
  "requestId": "req_011CbH1ZcxAYdrKDbao6eziy",
  "type": "assistant",
  "uuid": "53f66b04-2906-43ca-ae3c-b3f12913b8dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017BUSYk9nkr4asMmz8LpyHF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3105,
      "cache_read_input_tokens": 24805,
      "output_tokens": 301,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3105,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 301,
          "cache_read_input_tokens": 24805,
          "cache_creation_input_tokens": 3105,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3105
          },
          "type": "message"
        }
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

_source line 16 · 2026-05-22T04:54:35.703Z_

<details><summary>↩ Tool result · `toolu_01FwB8YDxdxeZsNNW5usKF6F`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "53f66b04-2906-43ca-ae3c-b3f12913b8dd",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "33bddd85-4f47-44de-9d12-bf8d758f6b2f",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "53f66b04-2906-43ca-ae3c-b3f12913b8dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 17_

```json
{
  "type": "last-prompt",
  "leafUuid": "33bddd85-4f47-44de-9d12-bf8d758f6b2f",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Runtime record

_source line 18_

```json
{
  "type": "ai-title",
  "aiTitle": "Sync experiment_plan.yaml with registry mappings",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Tool call

_source line 19 · 2026-05-22T04:54:47.495Z_

<details open><summary>🔧 Tool call — Grep · `toolu_017kcXrJniJmbMxAsyKxuVor`</summary>

```json
{
  "pattern": "^  id: (llama_phase1_gar_diag|llama_tg_s42|llama_lora_only_s42|llama_eval_s42|llama_ar_matched_eval|v7_tg_s123|v8b_ss_s123|eval_v7_tg_s123|eval_v8b_ss_s123|phase2_tg_s42_v8b_ss_fixed|phase2_tg_s42_v8b_resume)",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/registry.yaml",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "33bddd85-4f47-44de-9d12-bf8d758f6b2f",
  "isSidechain": false,
  "requestId": "req_011CbH1aDdz7kZCu957hF197",
  "type": "assistant",
  "uuid": "84ee57a9-ec70-4f8c-ba08-bdb89dd525d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J1s91vUkeeywSET1bRgqAh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 316,
      "cache_read_input_tokens": 27910,
      "output_tokens": 244,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 316,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 244,
          "cache_read_input_tokens": 27910,
          "cache_creation_input_tokens": 316,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 316
          },
          "type": "message"
        }
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

_source line 20 · 2026-05-22T04:54:47.506Z_

<details><summary>↩ Tool result · `toolu_017kcXrJniJmbMxAsyKxuVor`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "84ee57a9-ec70-4f8c-ba08-bdb89dd525d9",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "383d2db2-d31a-404f-8218-2b20c399e265",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "84ee57a9-ec70-4f8c-ba08-bdb89dd525d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-22T04:54:51.465Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01G6zN8fuhCAW6Tbvrj5gwJM`</summary>

```json
{
  "pattern": "llama_phase1_gar_diag|llama_tg_s42|llama_eval_s42|llama_ar_matched_eval|v7_tg_s123|v8b_ss_s123|eval_v7_tg_s123|eval_v8b_ss_s123|phase2_tg_s42_v8b_resume",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/registry.yaml",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "383d2db2-d31a-404f-8218-2b20c399e265",
  "isSidechain": false,
  "requestId": "req_011CbH1b6CYE3iw5KFZkRY8b",
  "type": "assistant",
  "uuid": "43539dff-10f2-4833-81e1-000e4ebd3c1e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AdAXxAxSs7cFifsZfrQjSZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 259,
      "cache_read_input_tokens": 28226,
      "output_tokens": 211,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 259,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 211,
          "cache_read_input_tokens": 28226,
          "cache_creation_input_tokens": 259,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 259
          },
          "type": "message"
        }
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

_source line 22 · 2026-05-22T04:54:51.478Z_

<details><summary>↩ Tool result · `toolu_01G6zN8fuhCAW6Tbvrj5gwJM`</summary>

```text
1046:  phase2_tg_s42_v8b_resume:
1071:      log_path: ~/runs/turn_residual_gating/phase2_tg_s42_v8b_resume.log
1208:  llama_phase1_gar_diag:
1233:      log_path: /root/turn_residual_gating/logs/llama_phase1_gar_diag.log
1255:  llama_tg_s42:
1263:    parent: llama_phase1_gar_diag
1267:        --data-dir data/ultrachat_8k --output-dir runs/phase2_llama_tg_s42 --gate-type
1281:      checkpoint_path: /root/turn_residual_gating/runs/phase2_llama_tg_s42
1336:  llama_eval_s42:
1344:    parent: llama_tg_s42
1347:        && cd /root/turn_residual_gating && bash scripts/eval_llama_tg_s42.sh 2>&1
1348:        | tee runs/eval_llama_tg_s42.log
1354:      checkpoint_source: runs/phase2_llama_tg_s42/epoch_2
1356:    checkpoint_path: runs/phase2_llama_tg_s42/epoch_2
1357:    log_path: runs/eval_llama_tg_s42.log
1415:    notes: 'INVALIDATED: Phantom duplicate of llama_tg_s42 (same PID 199643, same
1417:      Canonical entry is llama_tg_s42 (DONE/success).'
1466:  llama_ar_matched_eval:
1473:    parent: llama_eval_s42
1481:      checkpoint_source: phase2_llama_tg_s42
1525:  v8b_ss_s123:
1532:    parent: phase2_tg_s42_v8b_resume
1534:      command: bash scripts/launch_v8b_ss_s123.sh
1542:      checkpoint_path: /root/turn_residual_gating/checkpoints/tg_v8b_ss_s123
1543:      log_path: /root/turn_residual_gating/logs/v8b_ss_s123.log
1559:  v7_tg_s123:
1568:      command: bash scripts/launch_v7_tg_s123.sh
1577:      log_path: /root/turn_residual_gating/logs/v7_tg_s123.log
1582:    log_path: logs/v7_tg_s123.log
1630:  eval_v8b_ss_s123:
1636:      command: bash scripts/eval_v8b_ss_s123.sh
1641:      log_path: runs/eval_v8b_ss_s123/
1651:      checkpoint_source: checkpoints/tg_v8b_ss_s123/epoch_2
1653:      checkpoint_path: checkpoints/tg_v8b_ss_s123/epoch_2
1659:    parent: v7_tg_s123
1660:    log_path: ~/runs/turn_residual_gating/eval_v8b_ss_s123.log
1681:  eval_v7_tg_s123:
1687:      command: bash scripts/eval_v7_tg_s123.sh
1692:      log_path: /root/turn_residual_gating/logs/v7_tg_s123.log
1701:      checkpoint_source: v7_tg_s123
1708:    parent: v7_tg_s123
1735:    parent: llama_tg_s42
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "43539dff-10f2-4833-81e1-000e4ebd3c1e",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "9ea7769c-beed-45ff-be61-3a6bec947248",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "1046:  phase2_tg_s42_v8b_resume:\n1071:      log_path: ~/runs/turn_residual_gating/phase2_tg_s42_v8b_resume.log\n1208:  llama_phase1_gar_diag:\n1233:      log_path: /root/turn_residual_gating/logs/llama_phase1_gar_diag.log\n1255:  llama_tg_s42:\n1263:    parent: llama_phase1_gar_diag\n1267:        --data-dir data/ultrachat_8k --output-dir runs/phase2_llama_tg_s42 --gate-type\n1281:      checkpoint_path: /root/turn_residual_gating/runs/phase2_llama_tg_s42\n1336:  llama_eval_s42:\n1344:    parent: llama_tg_s42\n1347:        && cd /root/turn_residual_gating && bash scripts/eval_llama_tg_s42.sh 2>&1\n1348:        | tee runs/eval_llama_tg_s42.log\n1354:      checkpoint_source: runs/phase2_llama_tg_s42/epoch_2\n1356:    checkpoint_path: runs/phase2_llama_tg_s42/epoch_2\n1357:    log_path: runs/eval_llama_tg_s42.log\n1415:    notes: 'INVALIDATED: Phantom duplicate of llama_tg_s42 (same PID 199643, same\n1417:      Canonical entry is llama_tg_s42 (DONE/success).'\n1466:  llama_ar_matched_eval:\n1473:    parent: llama_eval_s42\n1481:      checkpoint_source: phase2_llama_tg_s42\n1525:  v8b_ss_s123:\n1532:    parent: phase2_tg_s42_v8b_resume\n1534:      command: bash scripts/launch_v8b_ss_s123.sh\n1542:      checkpoint_path: /root/turn_residual_gating/checkpoints/tg_v8b_ss_s123\n1543:      log_path: /root/turn_residual_gating/logs/v8b_ss_s123.log\n1559:  v7_tg_s123:\n1568:      command: bash scripts/launch_v7_tg_s123.sh\n1577:      log_path: /root/turn_residual_gating/logs/v7_tg_s123.log\n1582:    log_path: logs/v7_tg_s123.log\n1630:  eval_v8b_ss_s123:\n1636:      command: bash scripts/eval_v8b_ss_s123.sh\n1641:      log_path: runs/eval_v8b_ss_s123/\n1651:      checkpoint_source: checkpoints/tg_v8b_ss_s123/epoch_2\n1653:      checkpoint_path: checkpoints/tg_v8b_ss_s123/epoch_2\n1659:    parent: v7_tg_s123\n1660:    log_path: ~/runs/turn_residual_gating/eval_v8b_ss_s123.log\n1681:  eval_v7_tg_s123:\n1687:      command: bash scripts/eval_v7_tg_s123.sh\n1692:      log_path: /root/turn_residual_gating/logs/v7_tg_s123.log\n1701:      checkpoint_source: v7_tg_s123\n1708:    parent: v7_tg_s123\n1735:    parent: llama_tg_s42",
    "numLines": 42
  },
  "sourceToolAssistantUUID": "43539dff-10f2-4833-81e1-000e4ebd3c1e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-22T04:54:58.514Z_

All registry IDs exist. Now let me also check plan_015 and plan_017 status, and check the `llama_lora_only_s42` registry entry.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9ea7769c-beed-45ff-be61-3a6bec947248",
  "isSidechain": false,
  "requestId": "req_011CbH1bNyb8nh4soFHcRGPK",
  "type": "assistant",
  "uuid": "91a56fed-0c44-4c47-9d24-935c3ec1bbff",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NaeoHPxKS8rW3QWnNCUzHB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1194,
      "cache_read_input_tokens": 28485,
      "output_tokens": 170,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1194,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 170,
          "cache_read_input_tokens": 28485,
          "cache_creation_input_tokens": 1194,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1194
          },
          "type": "message"
        }
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

_source line 24 · 2026-05-22T04:55:00.043Z_

<details open><summary>🔧 Tool call — Grep · `toolu_014owxuvkn72xoYPYjT7wgou`</summary>

```json
{
  "pattern": "llama_lora_only_s42",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/registry.yaml",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "91a56fed-0c44-4c47-9d24-935c3ec1bbff",
  "isSidechain": false,
  "requestId": "req_011CbH1bNyb8nh4soFHcRGPK",
  "type": "assistant",
  "uuid": "8e04e1e3-583a-4451-8e2b-01f674d133db",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NaeoHPxKS8rW3QWnNCUzHB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1194,
      "cache_read_input_tokens": 28485,
      "output_tokens": 170,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1194,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 170,
          "cache_read_input_tokens": 28485,
          "cache_creation_input_tokens": 1194,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1194
          },
          "type": "message"
        }
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

_source line 25 · 2026-05-22T04:55:00.058Z_

<details><summary>↩ Tool result · `toolu_014owxuvkn72xoYPYjT7wgou`</summary>

```text
1727:  llama_lora_only_s42:
1737:      command: bash scripts/launch_llama_lora_only_s42.sh
1742:      log_path: ~/runs/turn_residual_gating/llama_lora_only_s42.log
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8e04e1e3-583a-4451-8e2b-01f674d133db",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "3d24e045-7e0c-4c70-bfb4-92912d91489e",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "1727:  llama_lora_only_s42:\n1737:      command: bash scripts/launch_llama_lora_only_s42.sh\n1742:      log_path: ~/runs/turn_residual_gating/llama_lora_only_s42.log",
    "numLines": 3
  },
  "sourceToolAssistantUUID": "8e04e1e3-583a-4451-8e2b-01f674d133db",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 26 · 2026-05-22T04:55:03.630Z_

All registry IDs confirmed to exist. Now let me check the current state of plan_009, plan_010, plan_012, plan_019, and plan_023 more carefully, and check if the experiment_plan supports multiple registry_ids.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3d24e045-7e0c-4c70-bfb4-92912d91489e",
  "isSidechain": false,
  "requestId": "req_011CbH1c1q8Yh1tt4GULnsrX",
  "type": "assistant",
  "uuid": "ffec4335-deaa-41d9-beaf-03412d7b7116",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CHsgh9RQBoeSRHTuAMLNnU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 253,
      "cache_read_input_tokens": 29679,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 253,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 178,
          "cache_read_input_tokens": 29679,
          "cache_creation_input_tokens": 253,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 253
          },
          "type": "message"
        }
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

_source line 27 · 2026-05-22T04:55:04.654Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01LS477C2JGm4XwXctnt78Pq`</summary>

```json
{
  "pattern": "registry_id",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ffec4335-deaa-41d9-beaf-03412d7b7116",
  "isSidechain": false,
  "requestId": "req_011CbH1c1q8Yh1tt4GULnsrX",
  "type": "assistant",
  "uuid": "3619677e-6c85-4c4b-a52a-b82bc305fd61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CHsgh9RQBoeSRHTuAMLNnU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 253,
      "cache_read_input_tokens": 29679,
      "output_tokens": 178,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 253,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 178,
          "cache_read_input_tokens": 29679,
          "cache_creation_input_tokens": 253,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 253
          },
          "type": "message"
        }
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

_source line 28 · 2026-05-22T04:55:04.670Z_

<details><summary>↩ Tool result · `toolu_01LS477C2JGm4XwXctnt78Pq`</summary>

```text
8:  registry_id: phase1_gar_diag
18:  registry_id: phase2_tg_s42_v7
27:  registry_id: phase2_ug_s42
36:  registry_id: phase2_lora_only_s42
47:  registry_id: phase2_4way_eval
57:  registry_id: analysis_gradient_conflict
68:  registry_id: analysis_attention_heatmap
79:  registry_id: phase2_4way_eval_heldout
105:  registry_id: llama_lora_only_s42
144:  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212
159:  registry_id: phase2_tg_s42_v8_schedsampling
169:  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058
181:  registry_id: phase2_tg_s42_v9_pcgrad
222:  registry_id: phase2_tg_s42_v8b_ss_fixed
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3619677e-6c85-4c4b-a52a-b82bc305fd61",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "6b1eb321-30f2-4535-b958-538881acb58d",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "8:  registry_id: phase1_gar_diag\n18:  registry_id: phase2_tg_s42_v7\n27:  registry_id: phase2_ug_s42\n36:  registry_id: phase2_lora_only_s42\n47:  registry_id: phase2_4way_eval\n57:  registry_id: analysis_gradient_conflict\n68:  registry_id: analysis_attention_heatmap\n79:  registry_id: phase2_4way_eval_heldout\n105:  registry_id: llama_lora_only_s42\n144:  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n159:  registry_id: phase2_tg_s42_v8_schedsampling\n169:  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n181:  registry_id: phase2_tg_s42_v9_pcgrad\n222:  registry_id: phase2_tg_s42_v8b_ss_fixed",
    "numLines": 14
  },
  "sourceToolAssistantUUID": "3619677e-6c85-4c4b-a52a-b82bc305fd61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 29 · 2026-05-22T04:55:04.693Z_

```json
{
  "parentUuid": "6b1eb321-30f2-4535-b958-538881acb58d",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "feb25008-c899-4366-8c4e-0045d15332f4",
  "timestamp": "2026-05-22T04:55:04.693Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 30 · 2026-05-22T04:55:12.732Z_

All existing `registry_id` fields are single strings. Let me also check if `compute_coverage_matrix` supports a list format by looking at how it's used.

Now I'll apply the edits. The plan entries that need changes:

- **plan_009** (line ~87): add `registry_id: llama_phase1_gar_diag`
- **plan_010** (line ~95): add `registry_id: llama_tg_s42`
- **plan_012** (line ~115): add `registry_id: llama_eval_s42`
- **plan_019** (line ~191): add `registry_id: v7_tg_s123`
- **plan_023** (line ~222): already has `phase2_tg_s42_v8b_ss_fixed`, update to `phase2_tg_s42_v8b_resume`

For plan_012 and plan_019, I'll use the primary registry_id as instructed (single value). For plan_023, since `phase2_tg_s42_v8b_resume` is the "actually successful version", it makes more sense to point to that one.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "feb25008-c899-4366-8c4e-0045d15332f4",
  "isSidechain": false,
  "requestId": "req_011CbH1cMZYKgD7PMGRCyfN6",
  "type": "assistant",
  "uuid": "dc37ad67-b38c-474b-b05c-0886b5aa04f6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q1dz5ZcYMKrQBBAx5aRqxm",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 566,
      "cache_read_input_tokens": 29932,
      "output_tokens": 566,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 566,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 566,
          "cache_read_input_tokens": 29932,
          "cache_creation_input_tokens": 566,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 566
          },
          "type": "message"
        }
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

_source line 31 · 2026-05-22T04:55:16.262Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01HTp6fsLCj7BsE1ujdrBB3c`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "old_string": "- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned",
  "new_string": "- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dc37ad67-b38c-474b-b05c-0886b5aa04f6",
  "isSidechain": false,
  "requestId": "req_011CbH1cMZYKgD7PMGRCyfN6",
  "type": "assistant",
  "uuid": "00776219-f13c-4991-b552-73dc0f5a3f11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Q1dz5ZcYMKrQBBAx5aRqxm",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 566,
      "cache_read_input_tokens": 29932,
      "output_tokens": 566,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 566,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 566,
          "cache_read_input_tokens": 29932,
          "cache_creation_input_tokens": 566,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 566
          },
          "type": "message"
        }
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

_source line 32 · 2026-05-22T04:55:16.291Z_

<details><summary>↩ Tool result · `toolu_01HTp6fsLCj7BsE1ujdrBB3c`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "00776219-f13c-4991-b552-73dc0f5a3f11",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "1582b83f-7cb5-4625-8531-b1ccd67adcef",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
    "oldString": "- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned",
    "newString": "- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag",
    "originalFile": "experiments:\n- id: plan_001\n  claim: C1\n  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: phase1_gar_diag\n  status: done\n- id: plan_002\n  claim: C2\n  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference\n    GAR 0.016\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_tg_s42_v7\n  status: done\n- id: plan_003\n  claim: C4\n  description: Uniform Gate ablation - isolate turn conditioning contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_ug_s42\n  status: done\n- id: plan_004\n  claim: C4\n  description: LoRA-only ablation - isolate gating mechanism contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_lora_only_s42\n  status: done\n- id: plan_005\n  claim: C4\n  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: phase2_4way_eval\n  status: done\n- id: plan_006\n  claim: C3\n  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR\n    gradient cos_sim + magnitude ratio\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  registry_id: analysis_gradient_conflict\n  status: done\n- id: plan_007\n  claim: C3\n  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: analysis_attention_heatmap\n  status: done\n- id: plan_008\n  claim: C2, C4\n  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000\n    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_005\n  status: planned\n  registry_id: phase2_4way_eval_heldout\n- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_ss_fixed\n",
    "structuredPatch": [
      {
        "oldStart": 85,
        "oldLines": 6,
        "newStart": 85,
        "newLines": 7,
        "lines": [
          "   gpu_budget_hours: 0.5",
          "   deps: []",
          "   status: planned",
          "+  registry_id: llama_phase1_gar_diag",
          " - id: plan_010",
          "   claim: C5",
          "   description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "00776219-f13c-4991-b552-73dc0f5a3f11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-22T04:55:21.607Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01JHBdLB9SLPjv5LtutAKh1w`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "old_string": "- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned",
  "new_string": "- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_tg_s42"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1582b83f-7cb5-4625-8531-b1ccd67adcef",
  "isSidechain": false,
  "requestId": "req_011CbH1dDBnX31q8S1526LVT",
  "type": "assistant",
  "uuid": "35b1e670-e022-45f4-aeb3-e486c2fba8cd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HeTyJLd8sjsdBPb2RvDf6p",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 638,
      "cache_read_input_tokens": 30498,
      "output_tokens": 306,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 638,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 306,
          "cache_read_input_tokens": 30498,
          "cache_creation_input_tokens": 638,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 638
          },
          "type": "message"
        }
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

_source line 34 · 2026-05-22T04:55:21.622Z_

<details><summary>↩ Tool result · `toolu_01JHBdLB9SLPjv5LtutAKh1w`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "35b1e670-e022-45f4-aeb3-e486c2fba8cd",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "281c55a1-2f67-41c4-a29d-dfdacfb9aeee",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
    "oldString": "- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned",
    "newString": "- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_tg_s42",
    "originalFile": "experiments:\n- id: plan_001\n  claim: C1\n  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: phase1_gar_diag\n  status: done\n- id: plan_002\n  claim: C2\n  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference\n    GAR 0.016\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_tg_s42_v7\n  status: done\n- id: plan_003\n  claim: C4\n  description: Uniform Gate ablation - isolate turn conditioning contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_ug_s42\n  status: done\n- id: plan_004\n  claim: C4\n  description: LoRA-only ablation - isolate gating mechanism contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_lora_only_s42\n  status: done\n- id: plan_005\n  claim: C4\n  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: phase2_4way_eval\n  status: done\n- id: plan_006\n  claim: C3\n  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR\n    gradient cos_sim + magnitude ratio\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  registry_id: analysis_gradient_conflict\n  status: done\n- id: plan_007\n  claim: C3\n  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: analysis_attention_heatmap\n  status: done\n- id: plan_008\n  claim: C2, C4\n  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000\n    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_005\n  status: planned\n  registry_id: phase2_4way_eval_heldout\n- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_ss_fixed\n",
    "structuredPatch": [
      {
        "oldStart": 94,
        "oldLines": 6,
        "newStart": 94,
        "newLines": 7,
        "lines": [
          "   deps:",
          "   - plan_009",
          "   status: planned",
          "+  registry_id: llama_tg_s42",
          " - id: plan_011",
          "   claim: C5",
          "   description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "35b1e670-e022-45f4-aeb3-e486c2fba8cd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 35_

```json
{
  "type": "last-prompt",
  "leafUuid": "281c55a1-2f67-41c4-a29d-dfdacfb9aeee",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Runtime record

_source line 36_

```json
{
  "type": "ai-title",
  "aiTitle": "Sync experiment_plan.yaml with registry mappings",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Tool call

_source line 37 · 2026-05-22T04:55:27.433Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01GtxCiHJKK3UyFexhpW3aeM`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "old_string": "- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned",
  "new_string": "- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n  registry_id: llama_eval_s42"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "281c55a1-2f67-41c4-a29d-dfdacfb9aeee",
  "isSidechain": false,
  "requestId": "req_011CbH1dbzV1rHGrbxGifKtW",
  "type": "assistant",
  "uuid": "607e1c47-8c97-4e86-82fc-c9b5c484289e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S1xN7SHmdqoY6foZgXvxq6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 359,
      "cache_read_input_tokens": 31136,
      "output_tokens": 341,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 359,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 341,
          "cache_read_input_tokens": 31136,
          "cache_creation_input_tokens": 359,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 359
          },
          "type": "message"
        }
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

_source line 38 · 2026-05-22T04:55:27.443Z_

<details><summary>↩ Tool result · `toolu_01GtxCiHJKK3UyFexhpW3aeM`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "607e1c47-8c97-4e86-82fc-c9b5c484289e",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "a21128f7-952b-4976-b93f-ce59b8044266",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
    "oldString": "- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned",
    "newString": "- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n  registry_id: llama_eval_s42",
    "originalFile": "experiments:\n- id: plan_001\n  claim: C1\n  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: phase1_gar_diag\n  status: done\n- id: plan_002\n  claim: C2\n  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference\n    GAR 0.016\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_tg_s42_v7\n  status: done\n- id: plan_003\n  claim: C4\n  description: Uniform Gate ablation - isolate turn conditioning contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_ug_s42\n  status: done\n- id: plan_004\n  claim: C4\n  description: LoRA-only ablation - isolate gating mechanism contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_lora_only_s42\n  status: done\n- id: plan_005\n  claim: C4\n  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: phase2_4way_eval\n  status: done\n- id: plan_006\n  claim: C3\n  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR\n    gradient cos_sim + magnitude ratio\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  registry_id: analysis_gradient_conflict\n  status: done\n- id: plan_007\n  claim: C3\n  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: analysis_attention_heatmap\n  status: done\n- id: plan_008\n  claim: C2, C4\n  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000\n    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_005\n  status: planned\n  registry_id: phase2_4way_eval_heldout\n- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_tg_s42\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_ss_fixed\n",
    "structuredPatch": [
      {
        "oldStart": 115,
        "oldLines": 6,
        "newStart": 115,
        "newLines": 7,
        "lines": [
          "   - plan_010",
          "   - plan_011",
          "   status: planned",
          "+  registry_id: llama_eval_s42",
          " - id: plan_013",
          "   claim: C3",
          "   description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "607e1c47-8c97-4e86-82fc-c9b5c484289e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-22T04:55:35.667Z_

<details open><summary>🔧 Tool call — Edit · `toolu_017hPeDgUnt9r3FeFcMzfyVL`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "old_string": "- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned",
  "new_string": "- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n  registry_id: v7_tg_s123"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a21128f7-952b-4976-b93f-ce59b8044266",
  "isSidechain": false,
  "requestId": "req_011CbH1e2uBj5cbmEagoqfrt",
  "type": "assistant",
  "uuid": "bf2c4487-a2b8-4e28-91fe-6109f453de56",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QfCFpW4sGid9g2QN6SzbZU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 394,
      "cache_read_input_tokens": 31495,
      "output_tokens": 360,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 394,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 360,
          "cache_read_input_tokens": 31495,
          "cache_creation_input_tokens": 394,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 394
          },
          "type": "message"
        }
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

_source line 40 · 2026-05-22T04:55:35.687Z_

<details><summary>↩ Tool result · `toolu_017hPeDgUnt9r3FeFcMzfyVL`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bf2c4487-a2b8-4e28-91fe-6109f453de56",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "d8ac5813-202f-4ea6-89da-108e96b6e9d2",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
    "oldString": "- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned",
    "newString": "- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n  registry_id: v7_tg_s123",
    "originalFile": "experiments:\n- id: plan_001\n  claim: C1\n  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: phase1_gar_diag\n  status: done\n- id: plan_002\n  claim: C2\n  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference\n    GAR 0.016\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_tg_s42_v7\n  status: done\n- id: plan_003\n  claim: C4\n  description: Uniform Gate ablation - isolate turn conditioning contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_ug_s42\n  status: done\n- id: plan_004\n  claim: C4\n  description: LoRA-only ablation - isolate gating mechanism contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_lora_only_s42\n  status: done\n- id: plan_005\n  claim: C4\n  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: phase2_4way_eval\n  status: done\n- id: plan_006\n  claim: C3\n  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR\n    gradient cos_sim + magnitude ratio\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  registry_id: analysis_gradient_conflict\n  status: done\n- id: plan_007\n  claim: C3\n  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: analysis_attention_heatmap\n  status: done\n- id: plan_008\n  claim: C2, C4\n  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000\n    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_005\n  status: planned\n  registry_id: phase2_4way_eval_heldout\n- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_tg_s42\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n  registry_id: llama_eval_s42\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_ss_fixed\n",
    "structuredPatch": [
      {
        "oldStart": 192,
        "oldLines": 6,
        "newStart": 192,
        "newLines": 7,
        "lines": [
          "   deps:",
          "   - plan_002",
          "   status: planned",
          "+  registry_id: v7_tg_s123",
          " - id: plan_020",
          "   claim: C4, MF6",
          "   description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "bf2c4487-a2b8-4e28-91fe-6109f453de56",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-22T04:55:39.550Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01WncoCMefigyMNWK4xxuRdq`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "old_string": "  registry_id: phase2_tg_s42_v8b_ss_fixed",
  "new_string": "  registry_id: phase2_tg_s42_v8b_resume"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d8ac5813-202f-4ea6-89da-108e96b6e9d2",
  "isSidechain": false,
  "requestId": "req_011CbH1eeBDtTAQJSXphUHdC",
  "type": "assistant",
  "uuid": "b987af8c-944a-41b6-9f85-ce47eafe6595",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0161NC6HSBxNeUUqEL6c5EUW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 413,
      "cache_read_input_tokens": 31889,
      "output_tokens": 182,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 413,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 182,
          "cache_read_input_tokens": 31889,
          "cache_creation_input_tokens": 413,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 413
          },
          "type": "message"
        }
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

_source line 42 · 2026-05-22T04:55:39.560Z_

<details><summary>↩ Tool result · `toolu_01WncoCMefigyMNWK4xxuRdq`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b987af8c-944a-41b6-9f85-ce47eafe6595",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "40156f5c-63d4-4ea9-a4c2-617585ecda7e",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
    "oldString": "  registry_id: phase2_tg_s42_v8b_ss_fixed",
    "newString": "  registry_id: phase2_tg_s42_v8b_resume",
    "originalFile": "experiments:\n- id: plan_001\n  claim: C1\n  description: Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: phase1_gar_diag\n  status: done\n- id: plan_002\n  claim: C2\n  description: ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference\n    GAR 0.016\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_tg_s42_v7\n  status: done\n- id: plan_003\n  claim: C4\n  description: Uniform Gate ablation - isolate turn conditioning contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_ug_s42\n  status: done\n- id: plan_004\n  claim: C4\n  description: LoRA-only ablation - isolate gating mechanism contribution\n  priority: P0\n  gpu_budget_hours: 6\n  deps:\n  - plan_001\n  registry_id: phase2_lora_only_s42\n  status: done\n- id: plan_005\n  claim: C4\n  description: Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: phase2_4way_eval\n  status: done\n- id: plan_006\n  claim: C3\n  description: Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR\n    gradient cos_sim + magnitude ratio\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  registry_id: analysis_gradient_conflict\n  status: done\n- id: plan_007\n  claim: C3\n  description: Attention heatmap visualization (4 models x 3 conversations x 28 layers)\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_002\n  - plan_003\n  - plan_004\n  registry_id: analysis_attention_heatmap\n  status: done\n- id: plan_008\n  claim: C2, C4\n  description: 'Held-out eval: create truly held-out eval set (50 convs, idx>=8000\n    from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_005\n  status: planned\n  registry_id: phase2_4way_eval_heldout\n- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_tg_s42\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n  registry_id: llama_eval_s42\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n  registry_id: v7_tg_s123\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_ss_fixed\n",
    "structuredPatch": [
      {
        "oldStart": 223,
        "oldLines": 4,
        "newStart": 223,
        "newLines": 4,
        "lines": [
          "   deps:",
          "   - plan_002",
          "   status: planned",
          "-  registry_id: phase2_tg_s42_v8b_ss_fixed",
          "+  registry_id: phase2_tg_s42_v8b_resume"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "b987af8c-944a-41b6-9f85-ce47eafe6595",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 43 · 2026-05-22T04:55:43.696Z_

All edits applied. Now let me verify the file looks correct and then call `compute_coverage_matrix`.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "40156f5c-63d4-4ea9-a4c2-617585ecda7e",
  "isSidechain": false,
  "requestId": "req_011CbH1ewvZm7LJTV9jCRNrJ",
  "type": "assistant",
  "uuid": "f4a994e7-160f-44d7-8af3-d068b1f0d530",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0168vSr8Sx92dc1zabgAMfJo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 235,
      "cache_read_input_tokens": 32302,
      "output_tokens": 145,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 145,
          "cache_read_input_tokens": 32302,
          "cache_creation_input_tokens": 235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 235
          },
          "type": "message"
        }
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

_source line 44 · 2026-05-22T04:55:44.306Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JyTLN5VzbKpqqEnmH1gxQg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
  "offset": 80,
  "limit": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f4a994e7-160f-44d7-8af3-d068b1f0d530",
  "isSidechain": false,
  "requestId": "req_011CbH1ewvZm7LJTV9jCRNrJ",
  "type": "assistant",
  "uuid": "734f07c7-1f55-4101-8331-9d3cd4e223a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0168vSr8Sx92dc1zabgAMfJo",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 235,
      "cache_read_input_tokens": 32302,
      "output_tokens": 145,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 145,
          "cache_read_input_tokens": 32302,
          "cache_creation_input_tokens": 235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 235
          },
          "type": "message"
        }
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

_source line 45 · 2026-05-22T04:55:44.321Z_

<details><summary>↩ Tool result · `toolu_01JyTLN5VzbKpqqEnmH1gxQg`</summary>

```text
80	- id: plan_009
81	  claim: C5
82	  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay
83	    exists on different architecture
84	  priority: P0
85	  gpu_budget_hours: 0.5
86	  deps: []
87	  status: planned
88	  registry_id: llama_phase1_gar_diag
89	- id: plan_010
90	  claim: C5
91	  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama
92	  priority: P0
93	  gpu_budget_hours: 7
94	  deps:
95	  - plan_009
96	  status: planned
97	  registry_id: llama_tg_s42
98	- id: plan_011
99	  claim: C5
100	  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation
101	    (D020)
102	  priority: P0
103	  gpu_budget_hours: 7
104	  deps:
105	  - plan_009
106	  status: planned
107	  registry_id: llama_lora_only_s42
108	- id: plan_012
109	  claim: C5
110	  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out
111	    data
112	  priority: P0
113	  gpu_budget_hours: 1
114	  deps:
115	  - plan_010
116	  - plan_011
117	  status: planned
118	  registry_id: llama_eval_s42
119	- id: plan_013
120	  claim: C3
121	  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition
122	    is model-agnostic
123	  priority: P1
124	  gpu_budget_hours: 0.5
125	  deps:
126	  - plan_010
127	  status: planned
128	- id: plan_014
129	  claim: W3
130	  description: Downstream task sanity check - simple instruction retention test across
131	    turns to link GAR to task performance
132	  priority: P2
133	  gpu_budget_hours: 1
134	  deps:
135	  - plan_005
136	  status: planned
137	- id: plan_015
138	  claim: C4, W7
139	  description: Statistical significance analysis - paired bootstrap CI from held-out
140	    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically
141	    supports 'zero benefit'. Addresses Dream W3 (single seed).
142	  priority: P1
143	  gpu_budget_hours: 0.5
144	  deps:
145	  - plan_008
146	  status: done
147	  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212
148	  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],
149	    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero
150	    benefit. W7 addressed.'
151	- id: plan_016
152	  claim: W8
153	  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled
154	    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).
155	    Test whether closing exposure bias gap narrows the 30x training-inference GAR
156	    gap. Constructive direction that upgrades paper from pure negative result.
157	  priority: P1
158	  gpu_budget_hours: 8
159	  deps:
160	  - plan_008
161	  status: planned
162	  registry_id: phase2_tg_s42_v8_schedsampling
163	- id: plan_017
164	  claim: R4
165	  description: Code-paper architecture verification - confirm ThreadGate implementation
166	    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code
167	    audit, no GPU.
168	  priority: P0
169	  gpu_budget_hours: 0
170	  deps: []
171	  status: done
172	  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058
173	  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote
174	    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'
175	- id: plan_018
176	  claim: C3, W8
177	  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for
178	    gate params only. If 30x gap persists after removing gradient conflict → causal
179	    evidence that exposure bias (not gradient competition) is the root cause.
180	  priority: P0
181	  gpu_budget_hours: 8
182	  deps:
183	  - plan_006
184	  registry_id: phase2_tg_s42_v9_pcgrad
185	  status: done
186	- id: plan_019
187	  claim: C2, MF5
188	  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.
189	    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.
190	  priority: P1
191	  gpu_budget_hours: 6
192	  deps:
193	  - plan_002
194	  status: planned
195	  registry_id: v7_tg_s123
196	- id: plan_020
197	  claim: C4, MF6
198	  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000
199	    from UltraChat). Boost bootstrap CI statistical power.
200	  priority: P1
201	  gpu_budget_hours: 2
202	  deps:
203	  - plan_008
204	  status: planned
205	- id: plan_022
206	  claim: C3, SF4
207	  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient
208	    competition trend under higher GAR weight. If budget allows, add λ=0.1.
209	  priority: P2
210	  gpu_budget_hours: 2
211	  deps:
212	  - plan_002
213	  status: planned
214	- id: plan_023
215	  claim: W8, C3
216	  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option
217	    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0
218	    (match v7). Tests whether training on model-generated text closes the 30x distribution
219	    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial
220	    remedy''. D026.'
221	  priority: P1
222	  gpu_budget_hours: 8
223	  deps:
224	  - plan_002
225	  status: planned
226	  registry_id: phase2_tg_s42_v8b_resume
227	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "734f07c7-1f55-4101-8331-9d3cd4e223a9",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "4dd0640f-53c6-45f5-a360-b46d853d0a98",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/experiment_plan.yaml",
      "content": "- id: plan_009\n  claim: C5\n  description: Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay\n    exists on different architecture\n  priority: P0\n  gpu_budget_hours: 0.5\n  deps: []\n  status: planned\n  registry_id: llama_phase1_gar_diag\n- id: plan_010\n  claim: C5\n  description: Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_tg_s42\n- id: plan_011\n  claim: C5\n  description: Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation\n    (D020)\n  priority: P0\n  gpu_budget_hours: 7\n  deps:\n  - plan_009\n  status: planned\n  registry_id: llama_lora_only_s42\n- id: plan_012\n  claim: C5\n  description: Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out\n    data\n  priority: P0\n  gpu_budget_hours: 1\n  deps:\n  - plan_010\n  - plan_011\n  status: planned\n  registry_id: llama_eval_s42\n- id: plan_013\n  claim: C3\n  description: Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition\n    is model-agnostic\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_010\n  status: planned\n- id: plan_014\n  claim: W3\n  description: Downstream task sanity check - simple instruction retention test across\n    turns to link GAR to task performance\n  priority: P2\n  gpu_budget_hours: 1\n  deps:\n  - plan_005\n  status: planned\n- id: plan_015\n  claim: C4, W7\n  description: Statistical significance analysis - paired bootstrap CI from held-out\n    eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically\n    supports 'zero benefit'. Addresses Dream W3 (single seed).\n  priority: P1\n  gpu_budget_hours: 0.5\n  deps:\n  - plan_008\n  status: done\n  registry_id: worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\n  result: 'PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036],\n    UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero\n    benefit. W7 addressed.'\n- id: plan_016\n  claim: W8\n  description: Exposure-bias mitigation test - train ThreadGate v7 with scheduled\n    sampling applied to GAR loss (mix teacher-forced + model-generated contexts).\n    Test whether closing exposure bias gap narrows the 30x training-inference GAR\n    gap. Constructive direction that upgrades paper from pure negative result.\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_008\n  status: planned\n  registry_id: phase2_tg_s42_v8_schedsampling\n- id: plan_017\n  claim: R4\n  description: Code-paper architecture verification - confirm ThreadGate implementation\n    matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code\n    audit, no GPU.\n  priority: P0\n  gpu_budget_hours: 0\n  deps: []\n  status: done\n  registry_id: worker_analysis_code_paper_arch_verify_20260519T144058\n  result: 'CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote\n    g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.'\n- id: plan_018\n  claim: C3, W8\n  description: PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for\n    gate params only. If 30x gap persists after removing gradient conflict → causal\n    evidence that exposure bias (not gradient competition) is the root cause.\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_006\n  registry_id: phase2_tg_s42_v9_pcgrad\n  status: done\n- id: plan_019\n  claim: C2, MF5\n  description: Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen.\n    Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\n  priority: P1\n  gpu_budget_hours: 6\n  deps:\n  - plan_002\n  status: planned\n  registry_id: v7_tg_s123\n- id: plan_020\n  claim: C4, MF6\n  description: Expanded eval set — increase from 50 to 200 conversations (idx>=7000\n    from UltraChat). Boost bootstrap CI statistical power.\n  priority: P1\n  gpu_budget_hours: 2\n  deps:\n  - plan_008\n  status: planned\n- id: plan_022\n  claim: C3, SF4\n  description: λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient\n    competition trend under higher GAR weight. If budget allows, add λ=0.1.\n  priority: P2\n  gpu_budget_hours: 2\n  deps:\n  - plan_002\n  status: planned\n- id: plan_023\n  claim: W8, C3\n  description: 'v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option\n    A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0\n    (match v7). Tests whether training on model-generated text closes the 30x distribution\n    shift gap. If successful, paper upgrades from pure negative to ''diagnosis + initial\n    remedy''. D026.'\n  priority: P1\n  gpu_budget_hours: 8\n  deps:\n  - plan_002\n  status: planned\n  registry_id: phase2_tg_s42_v8b_resume\n",
      "numLines": 148,
      "startLine": 80,
      "totalLines": 227
    }
  },
  "sourceToolAssistantUUID": "734f07c7-1f55-4101-8331-9d3cd4e223a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 46_

```json
{
  "type": "last-prompt",
  "leafUuid": "4dd0640f-53c6-45f5-a360-b46d853d0a98",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Runtime record

_source line 47_

```json
{
  "type": "ai-title",
  "aiTitle": "Sync experiment_plan.yaml with registry mappings",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Assistant

_source line 48 · 2026-05-22T04:55:47.721Z_

File looks correct. Now let me call `compute_coverage_matrix` to verify.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4dd0640f-53c6-45f5-a360-b46d853d0a98",
  "isSidechain": false,
  "requestId": "req_011CbH1fGtqChdCV286Yi37F",
  "type": "assistant",
  "uuid": "c4e3eda6-acff-4a1a-a869-761bd8eb2486",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B458f4nVAtiApTRpsGe6xX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2142,
      "cache_read_input_tokens": 32537,
      "output_tokens": 106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2142,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 106,
          "cache_read_input_tokens": 32537,
          "cache_creation_input_tokens": 2142,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2142
          },
          "type": "message"
        }
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

_source line 49 · 2026-05-22T04:55:48.336Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01ELpetXSptgKhpSDyVZF1VQ`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__compute_coverage_matrix",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c4e3eda6-acff-4a1a-a869-761bd8eb2486",
  "isSidechain": false,
  "requestId": "req_011CbH1fGtqChdCV286Yi37F",
  "type": "assistant",
  "uuid": "74837de3-0d91-4e52-9a8f-35e53907d42b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B458f4nVAtiApTRpsGe6xX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2142,
      "cache_read_input_tokens": 32537,
      "output_tokens": 106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2142,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 106,
          "cache_read_input_tokens": 32537,
          "cache_creation_input_tokens": 2142,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2142
          },
          "type": "message"
        }
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

_source line 50 · 2026-05-22T04:55:48.340Z_

<details><summary>↩ Tool result · `toolu_01ELpetXSptgKhpSDyVZF1VQ`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__compute_coverage_matrix"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "74837de3-0d91-4e52-9a8f-35e53907d42b",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "14242939-2321-4cd7-8d94-97efb552f903",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__compute_coverage_matrix"
    ],
    "query": "select:mcp__agent-ml-research__compute_coverage_matrix",
    "total_deferred_tools": 24
  },
  "sourceToolAssistantUUID": "74837de3-0d91-4e52-9a8f-35e53907d42b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 51 · 2026-05-22T04:55:48.421Z_

```json
{
  "parentUuid": "14242939-2321-4cd7-8d94-97efb552f903",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "2dfa11f9-40db-47b0-a66e-560ad8a26197",
  "timestamp": "2026-05-22T04:55:48.421Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Tool call

_source line 52 · 2026-05-22T04:55:51.126Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__compute_coverage_matrix · `toolu_01YVuCcVQgQszU8F1CeMF2WT`</summary>

```json
{
  "project": "turn_residual_gating"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2dfa11f9-40db-47b0-a66e-560ad8a26197",
  "isSidechain": false,
  "requestId": "req_011CbH1faR2wysbmc5GREbgW",
  "type": "assistant",
  "uuid": "b0972125-9277-49a5-8881-4ce0084752a6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DkehBYYvhjH39SVYTcYCfH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 429,
      "cache_read_input_tokens": 34679,
      "output_tokens": 71,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 429,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 71,
          "cache_read_input_tokens": 34679,
          "cache_creation_input_tokens": 429,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 429
          },
          "type": "message"
        }
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

_source line 53 · 2026-05-22T04:55:51.430Z_

<details><summary>↩ Tool result · `toolu_01YVuCcVQgQszU8F1CeMF2WT`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"claims\": [\"C1\", \"C2\", \"C2, C4\", \"C2, MF5\", \"C3\", \"C3, SF4\", \"C3, W8\", \"C4\", \"C4, MF6\", \"C4, W7\", \"C5\", \"R4\", \"W3\", \"W8\", \"W8, C3\"], \"matrix\": {\"C1\": {\"experiments\": [{\"id\": \"plan_001\", \"claim\": \"C1\", \"description\": \"Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [], \"registry_id\": \"phase1_gar_diag\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"turn1_avg_gar\": 0.0418, \"mid_turns_avg_gar\": 0.0122, \"relative_drop\": 0.708, \"num_conversations\": 5, \"num_turns\": 10, \"per_turn_avg_gar\": [0.0418, 0.0241, 0.0224, 0.013, 0.0133, 0.0086, 0.0078, 0.008, 0.0157, 0.0064]}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C2\": {\"experiments\": [{\"id\": \"plan_002\", \"claim\": \"C2\", \"description\": \"ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference GAR 0.016\", \"priority\": \"P0\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_001\"], \"registry_id\": \"phase2_tg_s42_v7\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_iid_ours_mid_gar\": 0.5035, \"eval_iid_dongre_mid_gar\": 0.0152, \"eval_iid_ppl\": 2.784, \"eval_heldout_ours_mid_gar\": 0.5035, \"eval_heldout_dongre_mid_gar\": 0.0152, \"eval_heldout_ppl\": 2.78, \"eval_modelgen_ours_mid_gar\": 0.0157, \"eval_modelgen_dongre_mid_gar\": 0.0194, \"eval_modelgen_ppl\": 1.36, \"gate_mean_final\": 0.9336, \"gate_std_final\": 0.0492}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C4\": {\"experiments\": [{\"id\": \"plan_003\", \"claim\": \"C4\", \"description\": \"Uniform Gate ablation - isolate turn conditioning contribution\", \"priority\": \"P0\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_001\"], \"registry_id\": \"phase2_ug_s42\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"epoch0_avg_loss\": 1.0019, \"epoch0_avg_ntp\": 0.9755, \"epoch0_avg_gar\": 0.0259, \"epoch0_avg_div\": 0.0005, \"epoch1_avg_loss\": 0.9447, \"epoch1_avg_ntp\": 0.9435, \"epoch1_avg_gar\": 0.0013, \"epoch1_avg_div\": 0, \"epoch2_avg_loss\": 0.9319, \"epoch2_avg_ntp\": 0.9309, \"epoch2_avg_gar\": 0.001, \"epoch2_avg_div\": 0, \"final_gate_mean\": 0.9598, \"final_gate_std\": 0.0518, \"final_gate_min\": 0.7773, \"final_gate_max\": 1, \"final_profile_L3\": 0.777, \"final_profile_L5\": 0.812, \"final_profile_L0\": 0.875, \"final_profile_L27\": 1, \"training_time_seconds\": 21994.5, \"training_time_hours\": 6.1, \"global_steps\": 7950, \"unexpected_per_layer_variation\": true, \"eval_modelgen_ours_mid_gar\": 0.0149, \"eval_modelgen_dongre_mid_gar\": 0.0185, \"eval_modelgen_ppl\": 1.396}}, {\"id\": \"plan_004\", \"claim\": \"C4\", \"description\": \"LoRA-only ablation - isolate gating mechanism contribution\", \"priority\": \"P0\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_001\"], \"registry_id\": \"phase2_lora_only_s42\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"epochs_completed\": 3, \"global_steps\": 3000, \"training_time_seconds\": 20588.6, \"training_time_hours\": 5.7, \"gate_fixed\": 1, \"gate_type_actual\": \"none\", \"final_lora_size_mb\": 20, \"eval_modelgen_ours_mid_gar\": 0.0245, \"eval_modelgen_dongre_mid_gar\": 0.0185, \"eval_modelgen_ppl\": 1.371}}, {\"id\": \"plan_005\", \"claim\": \"C4\", \"description\": \"Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_002\", \"plan_003\", \"plan_004\"], \"registry_id\": \"phase2_4way_eval\", \"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"base_ours_mid_gar\": 0.0107, \"base_ours_recovery_pp\": -0.15, \"base_dongre_mid_gar\": 0.003, \"base_dongre_recovery_pp\": -0.92, \"base_ppl\": 4.23, \"base_ntp\": 1.4162, \"tg_ours_mid_gar\": 0.4866, \"tg_ours_recovery_pp\": 47.44, \"tg_dongre_mid_gar\": 0.0157, \"tg_dongre_recovery_pp\": 0.35, \"tg_ppl\": 2.63, \"tg_ntp\": 0.9484, \"ug_ours_mid_gar\": 0.4923, \"ug_ours_recovery_pp\": 48.01, \"ug_dongre_mid_gar\": 0.013, \"ug_dongre_recovery_pp\": 0.08, \"ug_ppl\": 2.62, \"ug_ntp\": 0.9433, \"lora_ours_mid_gar\": 0.486, \"lora_ours_recovery_pp\": 47.39, \"lora_dongre_mid_gar\": 0.0137, \"lora_dongre_recovery_pp\": 0.15, \"lora_ppl\": 2.63, \"lora_ntp\": 0.9482, \"route_b_confirmed\": true, \"gating_incremental_benefit\": \"none\"}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 2, \"failed\": 1, \"orphaned\": 0}, \"total\": 3, \"coverage\": \"2/3\", \"coverage_pct\": 66.7}, \"C3\": {\"experiments\": [{\"id\": \"plan_006\", \"claim\": \"C3\", \"description\": \"Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR gradient cos_sim + magnitude ratio\", \"priority\": \"P0\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_002\"], \"registry_id\": \"analysis_gradient_conflict\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"epoch0_cos_sim\": -0.089, \"epoch1_cos_sim\": -0.054, \"epoch2_cos_sim\": -0.042, \"epoch0_neg_layers_pct\": 78.6, \"epoch1_neg_layers_pct\": 71.4, \"epoch2_neg_layers_pct\": 67.9, \"epoch0_mag_ratio\": 7.5, \"epoch1_mag_ratio\": 13.7, \"epoch2_mag_ratio\": 14.7}}, {\"id\": \"plan_007\", \"claim\": \"C3\", \"description\": \"Attention heatmap visualization (4 models x 3 conversations x 28 layers)\", \"priority\": \"P0\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_002\", \"plan_003\", \"plan_004\"], \"registry_id\": \"analysis_attention_heatmap\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"base_mean_goal_attn\": 0.0136, \"base_decay\": 0.875, \"tg_mean_goal_attn\": 0.0232, \"tg_decay\": 0.777, \"ug_mean_goal_attn\": 0.0216, \"ug_decay\": 0.803, \"lora_mean_goal_attn\": 0.0216, \"lora_decay\": 0.81, \"gating_incremental_benefit\": \"none\"}}, {\"id\": \"plan_013\", \"claim\": \"C3\", \"description\": \"Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition is model-agnostic\", \"priority\": \"P1\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_010\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 2, \"failed\": 0, \"orphaned\": 0}, \"total\": 3, \"coverage\": \"2/3\", \"coverage_pct\": 66.7}, \"C2, C4\": {\"experiments\": [{\"id\": \"plan_008\", \"claim\": \"C2, C4\", \"description\": \"Held-out eval: create truly held-out eval set (50 convs, idx>=8000 from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_005\"], \"status\": \"DONE\", \"registry_id\": \"phase2_4way_eval_heldout\", \"conclusion\": \"success\", \"metrics\": {\"base_ours_mid_gar\": 0.0128, \"base_ours_recovery_pp\": 0.06, \"base_dongre_mid_gar\": 0.0031, \"base_dongre_recovery_pp\": -0.91, \"base_ppl\": 4.34, \"base_ntp\": 1.4045, \"tg_ours_mid_gar\": 0.5035, \"tg_ours_recovery_pp\": 49.13, \"tg_dongre_mid_gar\": 0.0152, \"tg_dongre_recovery_pp\": 0.3, \"tg_ppl\": 2.78, \"tg_ntp\": 0.9771, \"ug_ours_mid_gar\": 0.5053, \"ug_ours_recovery_pp\": 49.31, \"ug_dongre_mid_gar\": 0.0124, \"ug_dongre_recovery_pp\": 0.02, \"ug_ppl\": 2.78, \"ug_ntp\": 0.9752, \"lora_ours_mid_gar\": 0.4978, \"lora_ours_recovery_pp\": 48.56, \"lora_dongre_mid_gar\": 0.0132, \"lora_dongre_recovery_pp\": 0.1, \"lora_ppl\": 2.78, \"lora_ntp\": 0.9771, \"three_way_convergence_confirmed\": true, \"gar_ours_spread_pp\": 0.75, \"ppl_spread\": 0, \"data_overlap\": false}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C5\": {\"experiments\": [{\"id\": \"plan_009\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay exists on different architecture\", \"priority\": \"P0\", \"gpu_budget_hours\": 0.5, \"deps\": [], \"status\": \"DONE\", \"registry_id\": \"llama_phase1_gar_diag\", \"conclusion\": \"success\", \"metrics\": {\"per_turn_gar\": {\"turn_1\": 0.0263, \"turn_2\": 0.0183, \"turn_3\": 0.0087, \"turn_4\": 0.0055, \"turn_5\": 0.006, \"turn_6\": 0.0035, \"turn_7\": 0.0038, \"turn_8\": 0.0037, \"turn_9\": 0.005, \"turn_10\": 0.0026}, \"t1_t10_decay_pct\": 90.1, \"t1_mid38_drop_pct\": 80.2, \"n_topics\": 5, \"model\": \"Meta-Llama-3.1-8B-Instruct\", \"mode\": \"gen\", \"n_conversations\": 5, \"n_turns\": 10}}, {\"id\": \"plan_010\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\", \"priority\": \"P0\", \"gpu_budget_hours\": 7, \"deps\": [\"plan_009\"], \"status\": \"DONE\", \"registry_id\": \"llama_tg_s42\", \"conclusion\": \"success\", \"metrics\": {\"epochs_completed\": 3, \"total_steps\": 3000, \"wall_clock_seconds\": 26212, \"wall_clock_hours\": 7.28, \"final_avg_loss\": 0.9233, \"final_avg_ntp\": 0.9224, \"final_avg_gar\": 0.0009, \"final_avg_div\": 0, \"final_gate_mean\": 0.9099, \"final_gate_std\": 0.0701, \"final_gate_min\": 0.7188, \"final_gate_max\": 0.9922, \"gate_profile_step3000\": {\"L0\": 0.957, \"L1\": 0.973, \"L2\": 0.977, \"L3\": 0.965, \"L4\": 0.992, \"L5\": 0.969, \"L6\": 0.957, \"L7\": 0.957, \"L8\": 0.961, \"L9\": 0.949, \"L10\": 0.938, \"L11\": 0.934, \"L12\": 0.969, \"L13\": 0.953, \"L14\": 0.957, \"L15\": 0.965, \"L16\": 0.953, \"L17\": 0.961, \"L18\": 0.922, \"L19\": 0.902, \"L20\": 0.883, \"L21\": 0.863, \"L22\": 0.836, \"L23\": 0.844, \"L24\": 0.809, \"L25\": 0.719, \"L26\": 0.762, \"L27\": 0.805, \"L28\": 0.801, \"L29\": 0.855, \"L30\": 0.898, \"L31\": 0.934}, \"checkpoint_size_gate_mb\": 4.2, \"checkpoint_size_lora_mb\": 26, \"gpu\": \"NVIDIA RTX PRO 6000 Blackwell\", \"vram_gb\": 102, \"mem_used_gb\": 63.4}}, {\"id\": \"plan_011\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation (D020)\", \"priority\": \"P0\", \"gpu_budget_hours\": 7, \"deps\": [\"plan_009\"], \"status\": \"RUNNING\", \"registry_id\": \"llama_lora_only_s42\"}, {\"id\": \"plan_012\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out data\", \"priority\": \"P0\", \"gpu_budget_hours\": 1, \"deps\": [\"plan_010\", \"plan_011\"], \"status\": \"DONE\", \"registry_id\": \"llama_eval_s42\", \"conclusion\": \"success\", \"metrics\": {\"tf_base\": {\"gar_ours\": 0.0166, \"ngar_ours\": 0.3882, \"gar_dongre\": 0.0038, \"ngar_dongre\": 0.163, \"ppl\": 3.45, \"N\": 50, \"T\": 4}, \"tf_tg\": {\"gar_ours\": 0.4836, \"ngar_ours\": 11.8818, \"gar_dongre\": 0.018, \"ngar_dongre\": 0.7922, \"ppl\": 2.57, \"N\": 50, \"T\": 4}, \"ar_base\": {\"gar_ours\": 0.0086, \"ngar_ours\": 0.0798, \"gar_dongre\": 0.0118, \"ngar_dongre\": 0.1265, \"ppl\": 1.24, \"N\": 5, \"T\": 10}, \"ar_tg\": {\"gar_ours\": 0.0304, \"ngar_ours\": 0.2632, \"gar_dongre\": 0.0217, \"ngar_dongre\": 0.2459, \"ppl\": 1.32, \"N\": 5, \"T\": 10}, \"gap_ratio_tg_ours\": 15.9, \"gap_ratio_base_ours\": 1.93, \"gap_ratio_tg_dongre\": 0.83, \"vs_qwen_v7_gap_ratio\": 32.1, \"baseline_mid_gar\": 0.0122}}], \"counts\": {\"planned\": 0, \"running\": 1, \"done\": 3, \"failed\": 0, \"orphaned\": 0}, \"total\": 4, \"coverage\": \"3/4\", \"coverage_pct\": 75.0}, \"W3\": {\"experiments\": [{\"id\": \"plan_014\", \"claim\": \"W3\", \"description\": \"Downstream task sanity check - simple instruction retention test across turns to link GAR to task performance\", \"priority\": \"P2\", \"gpu_budget_hours\": 1, \"deps\": [\"plan_005\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"C4, W7\": {\"experiments\": [{\"id\": \"plan_015\", \"claim\": \"C4, W7\", \"description\": \"Statistical significance analysis - paired bootstrap CI from held-out eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically supports 'zero benefit'. Addresses Dream W3 (single seed).\", \"priority\": \"P1\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_008\"], \"status\": \"orphaned\", \"registry_id\": \"worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\", \"result\": \"PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036], UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero benefit. W7 addressed.\"}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 1}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"W8\": {\"experiments\": [{\"id\": \"plan_016\", \"claim\": \"W8\", \"description\": \"Exposure-bias mitigation test - train ThreadGate v7 with scheduled sampling applied to GAR loss (mix teacher-forced + model-generated contexts). Test whether closing exposure bias gap narrows the 30x training-inference GAR gap. Constructive direction that upgrades paper from pure negative result.\", \"priority\": \"P1\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_008\"], \"status\": \"DONE\", \"registry_id\": \"phase2_tg_s42_v8_schedsampling\", \"conclusion\": \"failed\", \"metrics\": {\"killed_at_microstep\": 1950, \"total_microsteps\": 24000, \"completion_pct\": 8.1, \"global_step_approx\": 244, \"total_global_steps\": 3000, \"ss_steps_observed\": 1, \"tf_lgar_mean_step850_1400\": 0.0062, \"tf_lgar_std\": 0.0082, \"tf_lgar_collapse_step\": 800, \"gate_mean_final\": 0.93, \"ss_ratio_at_kill\": 0.081, \"crash_reason\": \"killed by director: SS path code bug (D026) makes experiment invalid, GPU needed for PCGrad\", \"design_flaw_ss_ramp_too_slow\": true, \"design_flaw_no_ss_tf_separate_logging\": true}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 0, \"failed\": 1, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"R4\": {\"experiments\": [{\"id\": \"plan_017\", \"claim\": \"R4\", \"description\": \"Code-paper architecture verification - confirm ThreadGate implementation matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code audit, no GPU.\", \"priority\": \"P0\", \"gpu_budget_hours\": 0, \"deps\": [], \"status\": \"orphaned\", \"registry_id\": \"worker_analysis_code_paper_arch_verify_20260519T144058\", \"result\": \"CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.\"}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 1}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"C3, W8\": {\"experiments\": [{\"id\": \"plan_018\", \"claim\": \"C3, W8\", \"description\": \"PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for gate params only. If 30x gap persists after removing gradient conflict → causal evidence that exposure bias (not gradient competition) is the root cause.\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_006\"], \"registry_id\": \"phase2_tg_s42_v9_pcgrad\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_iid_ours_mid_gar\": 0.5002, \"eval_iid_dongre_mid_gar\": 0.0123, \"eval_iid_ppl\": 2.78, \"eval_iid_ntp\": 0.9752, \"eval_heldout_ours_mid_gar\": 0.5002, \"eval_heldout_dongre_mid_gar\": 0.0123, \"eval_heldout_ppl\": 2.78, \"eval_heldout_ntp\": 0.9752, \"eval_modelgen_ours_mid_gar\": 0.0151, \"eval_modelgen_dongre_mid_gar\": 0.0173, \"eval_modelgen_ppl\": 1.5, \"vs_v7_iid_ppl_diff\": 0.004, \"vs_v7_iid_gar_diff\": -0.0033}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C2, MF5\": {\"experiments\": [{\"id\": \"plan_019\", \"claim\": \"C2, MF5\", \"description\": \"Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen. Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\", \"priority\": \"P1\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_002\"], \"status\": \"DONE\", \"registry_id\": \"v7_tg_s123\", \"conclusion\": \"success\", \"metrics\": {\"epoch_1\": {\"avg_loss\": 0.9447, \"avg_ntp_loss\": 0.9434, \"avg_gar_loss\": 0.0013, \"avg_div_loss\": 0}, \"epoch_2\": {\"avg_loss\": 0.9315, \"avg_ntp_loss\": 0.9305, \"avg_gar_loss\": 0.001, \"avg_div_loss\": 0}, \"final_gate\": {\"mean\": 0.9467, \"std\": 0.051, \"min\": 0.793, \"max\": 1}, \"final_gate_profile\": {\"L0\": 0.883, \"L1\": 0.793, \"L2\": 0.996, \"L3\": 0.988, \"L4\": 0.984, \"L5\": 0.797, \"L6\": 0.961, \"L7\": 0.918, \"L8\": 0.965, \"L9\": 0.934, \"L10\": 0.969, \"L11\": 0.918, \"L12\": 0.926, \"L13\": 0.941, \"L14\": 0.93, \"L15\": 0.965, \"L16\": 0.941, \"L17\": 0.91, \"L18\": 0.961, \"L19\": 0.965, \"L20\": 0.973, \"L21\": 0.988, \"L22\": 0.969, \"L23\": 0.98, \"L24\": 0.98, \"L25\": 0.984, \"L26\": 0.988, \"L27\": 1}, \"training_time_s\": 21425.2}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C4, MF6\": {\"experiments\": [{\"id\": \"plan_020\", \"claim\": \"C4, MF6\", \"description\": \"Expanded eval set — increase from 50 to 200 conversations (idx>=7000 from UltraChat). Boost bootstrap CI statistical power.\", \"priority\": \"P1\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_008\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"C3, SF4\": {\"experiments\": [{\"id\": \"plan_022\", \"claim\": \"C3, SF4\", \"description\": \"λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient competition trend under higher GAR weight. If budget allows, add λ=0.1.\", \"priority\": \"P2\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_002\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"W8, C3\": {\"experiments\": [{\"id\": \"plan_023\", \"claim\": \"W8, C3\", \"description\": \"v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0 (match v7). Tests whether training on model-generated text closes the 30x distribution shift gap. If successful, paper upgrades from pure negative to 'diagnosis + initial remedy'. D026.\", \"priority\": \"P1\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_002\"], \"status\": \"DONE\", \"registry_id\": \"phase2_tg_s42_v8b_resume\", \"conclusion\": \"success\", \"metrics\": {\"training\": {\"total_steps\": 3000, \"epochs_completed\": 3, \"wall_clock_hours\": 8.1, \"final_loss\": 0.933, \"final_ntp_loss\": 0.9322, \"final_gar_loss\": 0.0008, \"final_gate_mean\": 0.9586, \"final_gate_std\": 0.0582, \"ss_ratio\": 0.5}, \"eval_iid\": {\"gar_ours\": 0.4983, \"gar_dongre\": 0.3855, \"ppl\": 2.78}, \"eval_modelgen\": {\"gar_ours\": 0.3177, \"gar_dongre\": 0.3533, \"ppl\": 1.38}, \"vs_v7\": {\"iid_gar_ours_delta\": -0.005, \"modelgen_gar_ours_delta\": 0.302, \"gap_ratio_v7\": 32, \"gap_ratio_v8b\": 1.57}}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}}, \"unassigned\": [], \"summary\": {\"total_experiments\": 22, \"total_claims\": 15, \"counts\": {\"planned\": 4, \"running\": 1, \"done\": 13, \"failed\": 2, \"orphaned\": 2}, \"coverage\": \"13/22\", \"coverage_pct\": 59.1, \"unassigned\": 0}}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b0972125-9277-49a5-8881-4ce0084752a6",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "cb8b0eca-9670-43bd-b832-e2b353e6873f",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"claims\\\": [\\\"C1\\\", \\\"C2\\\", \\\"C2, C4\\\", \\\"C2, MF5\\\", \\\"C3\\\", \\\"C3, SF4\\\", \\\"C3, W8\\\", \\\"C4\\\", \\\"C4, MF6\\\", \\\"C4, W7\\\", \\\"C5\\\", \\\"R4\\\", \\\"W3\\\", \\\"W8\\\", \\\"W8, C3\\\"], \\\"matrix\\\": {\\\"C1\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_001\\\", \\\"claim\\\": \\\"C1\\\", \\\"description\\\": \\\"Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [], \\\"registry_id\\\": \\\"phase1_gar_diag\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"turn1_avg_gar\\\": 0.0418, \\\"mid_turns_avg_gar\\\": 0.0122, \\\"relative_drop\\\": 0.708, \\\"num_conversations\\\": 5, \\\"num_turns\\\": 10, \\\"per_turn_avg_gar\\\": [0.0418, 0.0241, 0.0224, 0.013, 0.0133, 0.0086, 0.0078, 0.008, 0.0157, 0.0064]}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 1, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"1/1\\\", \\\"coverage_pct\\\": 100.0}, \\\"C2\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_002\\\", \\\"claim\\\": \\\"C2\\\", \\\"description\\\": \\\"ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference GAR 0.016\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 6, \\\"deps\\\": [\\\"plan_001\\\"], \\\"registry_id\\\": \\\"phase2_tg_s42_v7\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_iid_ours_mid_gar\\\": 0.5035, \\\"eval_iid_dongre_mid_gar\\\": 0.0152, \\\"eval_iid_ppl\\\": 2.784, \\\"eval_heldout_ours_mid_gar\\\": 0.5035, \\\"eval_heldout_dongre_mid_gar\\\": 0.0152, \\\"eval_heldout_ppl\\\": 2.78, \\\"eval_modelgen_ours_mid_gar\\\": 0.0157, \\\"eval_modelgen_dongre_mid_gar\\\": 0.0194, \\\"eval_modelgen_ppl\\\": 1.36, \\\"gate_mean_final\\\": 0.9336, \\\"gate_std_final\\\": 0.0492}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 1, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"1/1\\\", \\\"coverage_pct\\\": 100.0}, \\\"C4\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_003\\\", \\\"claim\\\": \\\"C4\\\", \\\"description\\\": \\\"Uniform Gate ablation - isolate turn conditioning contribution\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 6, \\\"deps\\\": [\\\"plan_001\\\"], \\\"registry_id\\\": \\\"phase2_ug_s42\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"epoch0_avg_loss\\\": 1.0019, \\\"epoch0_avg_ntp\\\": 0.9755, \\\"epoch0_avg_gar\\\": 0.0259, \\\"epoch0_avg_div\\\": 0.0005, \\\"epoch1_avg_loss\\\": 0.9447, \\\"epoch1_avg_ntp\\\": 0.9435, \\\"epoch1_avg_gar\\\": 0.0013, \\\"epoch1_avg_div\\\": 0, \\\"epoch2_avg_loss\\\": 0.9319, \\\"epoch2_avg_ntp\\\": 0.9309, \\\"epoch2_avg_gar\\\": 0.001, \\\"epoch2_avg_div\\\": 0, \\\"final_gate_mean\\\": 0.9598, \\\"final_gate_std\\\": 0.0518, \\\"final_gate_min\\\": 0.7773, \\\"final_gate_max\\\": 1, \\\"final_profile_L3\\\": 0.777, \\\"final_profile_L5\\\": 0.812, \\\"final_profile_L0\\\": 0.875, \\\"final_profile_L27\\\": 1, \\\"training_time_seconds\\\": 21994.5, \\\"training_time_hours\\\": 6.1, \\\"global_steps\\\": 7950, \\\"unexpected_per_layer_variation\\\": true, \\\"eval_modelgen_ours_mid_gar\\\": 0.0149, \\\"eval_modelgen_dongre_mid_gar\\\": 0.0185, \\\"eval_modelgen_ppl\\\": 1.396}}, {\\\"id\\\": \\\"plan_004\\\", \\\"claim\\\": \\\"C4\\\", \\\"description\\\": \\\"LoRA-only ablation - isolate gating mechanism contribution\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 6, \\\"deps\\\": [\\\"plan_001\\\"], \\\"registry_id\\\": \\\"phase2_lora_only_s42\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"epochs_completed\\\": 3, \\\"global_steps\\\": 3000, \\\"training_time_seconds\\\": 20588.6, \\\"training_time_hours\\\": 5.7, \\\"gate_fixed\\\": 1, \\\"gate_type_actual\\\": \\\"none\\\", \\\"final_lora_size_mb\\\": 20, \\\"eval_modelgen_ours_mid_gar\\\": 0.0245, \\\"eval_modelgen_dongre_mid_gar\\\": 0.0185, \\\"eval_modelgen_ppl\\\": 1.371}}, {\\\"id\\\": \\\"plan_005\\\", \\\"claim\\\": \\\"C4\\\", \\\"description\\\": \\\"Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [\\\"plan_002\\\", \\\"plan_003\\\", \\\"plan_004\\\"], \\\"registry_id\\\": \\\"phase2_4way_eval\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"base_ours_mid_gar\\\": 0.0107, \\\"base_ours_recovery_pp\\\": -0.15, \\\"base_dongre_mid_gar\\\": 0.003, \\\"base_dongre_recovery_pp\\\": -0.92, \\\"base_ppl\\\": 4.23, \\\"base_ntp\\\": 1.4162, \\\"tg_ours_mid_gar\\\": 0.4866, \\\"tg_ours_recovery_pp\\\": 47.44, \\\"tg_dongre_mid_gar\\\": 0.0157, \\\"tg_dongre_recovery_pp\\\": 0.35, \\\"tg_ppl\\\": 2.63, \\\"tg_ntp\\\": 0.9484, \\\"ug_ours_mid_gar\\\": 0.4923, \\\"ug_ours_recovery_pp\\\": 48.01, \\\"ug_dongre_mid_gar\\\": 0.013, \\\"ug_dongre_recovery_pp\\\": 0.08, \\\"ug_ppl\\\": 2.62, \\\"ug_ntp\\\": 0.9433, \\\"lora_ours_mid_gar\\\": 0.486, \\\"lora_ours_recovery_pp\\\": 47.39, \\\"lora_dongre_mid_gar\\\": 0.0137, \\\"lora_dongre_recovery_pp\\\": 0.15, \\\"lora_ppl\\\": 2.63, \\\"lora_ntp\\\": 0.9482, \\\"route_b_confirmed\\\": true, \\\"gating_incremental_benefit\\\": \\\"none\\\"}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 2, \\\"failed\\\": 1, \\\"orphaned\\\": 0}, \\\"total\\\": 3, \\\"coverage\\\": \\\"2/3\\\", \\\"coverage_pct\\\": 66.7}, \\\"C3\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_006\\\", \\\"claim\\\": \\\"C3\\\", \\\"description\\\": \\\"Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR gradient cos_sim + magnitude ratio\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 0.5, \\\"deps\\\": [\\\"plan_002\\\"], \\\"registry_id\\\": \\\"analysis_gradient_conflict\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"epoch0_cos_sim\\\": -0.089, \\\"epoch1_cos_sim\\\": -0.054, \\\"epoch2_cos_sim\\\": -0.042, \\\"epoch0_neg_layers_pct\\\": 78.6, \\\"epoch1_neg_layers_pct\\\": 71.4, \\\"epoch2_neg_layers_pct\\\": 67.9, \\\"epoch0_mag_ratio\\\": 7.5, \\\"epoch1_mag_ratio\\\": 13.7, \\\"epoch2_mag_ratio\\\": 14.7}}, {\\\"id\\\": \\\"plan_007\\\", \\\"claim\\\": \\\"C3\\\", \\\"description\\\": \\\"Attention heatmap visualization (4 models x 3 conversations x 28 layers)\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 0.5, \\\"deps\\\": [\\\"plan_002\\\", \\\"plan_003\\\", \\\"plan_004\\\"], \\\"registry_id\\\": \\\"analysis_attention_heatmap\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"base_mean_goal_attn\\\": 0.0136, \\\"base_decay\\\": 0.875, \\\"tg_mean_goal_attn\\\": 0.0232, \\\"tg_decay\\\": 0.777, \\\"ug_mean_goal_attn\\\": 0.0216, \\\"ug_decay\\\": 0.803, \\\"lora_mean_goal_attn\\\": 0.0216, \\\"lora_decay\\\": 0.81, \\\"gating_incremental_benefit\\\": \\\"none\\\"}}, {\\\"id\\\": \\\"plan_013\\\", \\\"claim\\\": \\\"C3\\\", \\\"description\\\": \\\"Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition is model-agnostic\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 0.5, \\\"deps\\\": [\\\"plan_010\\\"], \\\"status\\\": \\\"planned\\\"}], \\\"counts\\\": {\\\"planned\\\": 1, \\\"running\\\": 0, \\\"done\\\": 2, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 3, \\\"coverage\\\": \\\"2/3\\\", \\\"coverage_pct\\\": 66.7}, \\\"C2, C4\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_008\\\", \\\"claim\\\": \\\"C2, C4\\\", \\\"description\\\": \\\"Held-out eval: create truly held-out eval set (50 convs, idx>=8000 from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [\\\"plan_005\\\"], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"phase2_4way_eval_heldout\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"base_ours_mid_gar\\\": 0.0128, \\\"base_ours_recovery_pp\\\": 0.06, \\\"base_dongre_mid_gar\\\": 0.0031, \\\"base_dongre_recovery_pp\\\": -0.91, \\\"base_ppl\\\": 4.34, \\\"base_ntp\\\": 1.4045, \\\"tg_ours_mid_gar\\\": 0.5035, \\\"tg_ours_recovery_pp\\\": 49.13, \\\"tg_dongre_mid_gar\\\": 0.0152, \\\"tg_dongre_recovery_pp\\\": 0.3, \\\"tg_ppl\\\": 2.78, \\\"tg_ntp\\\": 0.9771, \\\"ug_ours_mid_gar\\\": 0.5053, \\\"ug_ours_recovery_pp\\\": 49.31, \\\"ug_dongre_mid_gar\\\": 0.0124, \\\"ug_dongre_recovery_pp\\\": 0.02, \\\"ug_ppl\\\": 2.78, \\\"ug_ntp\\\": 0.9752, \\\"lora_ours_mid_gar\\\": 0.4978, \\\"lora_ours_recovery_pp\\\": 48.56, \\\"lora_dongre_mid_gar\\\": 0.0132, \\\"lora_dongre_recovery_pp\\\": 0.1, \\\"lora_ppl\\\": 2.78, \\\"lora_ntp\\\": 0.9771, \\\"three_way_convergence_confirmed\\\": true, \\\"gar_ours_spread_pp\\\": 0.75, \\\"ppl_spread\\\": 0, \\\"data_overlap\\\": false}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 1, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"1/1\\\", \\\"coverage_pct\\\": 100.0}, \\\"C5\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_009\\\", \\\"claim\\\": \\\"C5\\\", \\\"description\\\": \\\"Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay exists on different architecture\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 0.5, \\\"deps\\\": [], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"llama_phase1_gar_diag\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"per_turn_gar\\\": {\\\"turn_1\\\": 0.0263, \\\"turn_2\\\": 0.0183, \\\"turn_3\\\": 0.0087, \\\"turn_4\\\": 0.0055, \\\"turn_5\\\": 0.006, \\\"turn_6\\\": 0.0035, \\\"turn_7\\\": 0.0038, \\\"turn_8\\\": 0.0037, \\\"turn_9\\\": 0.005, \\\"turn_10\\\": 0.0026}, \\\"t1_t10_decay_pct\\\": 90.1, \\\"t1_mid38_drop_pct\\\": 80.2, \\\"n_topics\\\": 5, \\\"model\\\": \\\"Meta-Llama-3.1-8B-Instruct\\\", \\\"mode\\\": \\\"gen\\\", \\\"n_conversations\\\": 5, \\\"n_turns\\\": 10}}, {\\\"id\\\": \\\"plan_010\\\", \\\"claim\\\": \\\"C5\\\", \\\"description\\\": \\\"Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 7, \\\"deps\\\": [\\\"plan_009\\\"], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"llama_tg_s42\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"epochs_completed\\\": 3, \\\"total_steps\\\": 3000, \\\"wall_clock_seconds\\\": 26212, \\\"wall_clock_hours\\\": 7.28, \\\"final_avg_loss\\\": 0.9233, \\\"final_avg_ntp\\\": 0.9224, \\\"final_avg_gar\\\": 0.0009, \\\"final_avg_div\\\": 0, \\\"final_gate_mean\\\": 0.9099, \\\"final_gate_std\\\": 0.0701, \\\"final_gate_min\\\": 0.7188, \\\"final_gate_max\\\": 0.9922, \\\"gate_profile_step3000\\\": {\\\"L0\\\": 0.957, \\\"L1\\\": 0.973, \\\"L2\\\": 0.977, \\\"L3\\\": 0.965, \\\"L4\\\": 0.992, \\\"L5\\\": 0.969, \\\"L6\\\": 0.957, \\\"L7\\\": 0.957, \\\"L8\\\": 0.961, \\\"L9\\\": 0.949, \\\"L10\\\": 0.938, \\\"L11\\\": 0.934, \\\"L12\\\": 0.969, \\\"L13\\\": 0.953, \\\"L14\\\": 0.957, \\\"L15\\\": 0.965, \\\"L16\\\": 0.953, \\\"L17\\\": 0.961, \\\"L18\\\": 0.922, \\\"L19\\\": 0.902, \\\"L20\\\": 0.883, \\\"L21\\\": 0.863, \\\"L22\\\": 0.836, \\\"L23\\\": 0.844, \\\"L24\\\": 0.809, \\\"L25\\\": 0.719, \\\"L26\\\": 0.762, \\\"L27\\\": 0.805, \\\"L28\\\": 0.801, \\\"L29\\\": 0.855, \\\"L30\\\": 0.898, \\\"L31\\\": 0.934}, \\\"checkpoint_size_gate_mb\\\": 4.2, \\\"checkpoint_size_lora_mb\\\": 26, \\\"gpu\\\": \\\"NVIDIA RTX PRO 6000 Blackwell\\\", \\\"vram_gb\\\": 102, \\\"mem_used_gb\\\": 63.4}}, {\\\"id\\\": \\\"plan_011\\\", \\\"claim\\\": \\\"C5\\\", \\\"description\\\": \\\"Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation (D020)\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 7, \\\"deps\\\": [\\\"plan_009\\\"], \\\"status\\\": \\\"RUNNING\\\", \\\"registry_id\\\": \\\"llama_lora_only_s42\\\"}, {\\\"id\\\": \\\"plan_012\\\", \\\"claim\\\": \\\"C5\\\", \\\"description\\\": \\\"Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out data\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 1, \\\"deps\\\": [\\\"plan_010\\\", \\\"plan_011\\\"], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"llama_eval_s42\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"tf_base\\\": {\\\"gar_ours\\\": 0.0166, \\\"ngar_ours\\\": 0.3882, \\\"gar_dongre\\\": 0.0038, \\\"ngar_dongre\\\": 0.163, \\\"ppl\\\": 3.45, \\\"N\\\": 50, \\\"T\\\": 4}, \\\"tf_tg\\\": {\\\"gar_ours\\\": 0.4836, \\\"ngar_ours\\\": 11.8818, \\\"gar_dongre\\\": 0.018, \\\"ngar_dongre\\\": 0.7922, \\\"ppl\\\": 2.57, \\\"N\\\": 50, \\\"T\\\": 4}, \\\"ar_base\\\": {\\\"gar_ours\\\": 0.0086, \\\"ngar_ours\\\": 0.0798, \\\"gar_dongre\\\": 0.0118, \\\"ngar_dongre\\\": 0.1265, \\\"ppl\\\": 1.24, \\\"N\\\": 5, \\\"T\\\": 10}, \\\"ar_tg\\\": {\\\"gar_ours\\\": 0.0304, \\\"ngar_ours\\\": 0.2632, \\\"gar_dongre\\\": 0.0217, \\\"ngar_dongre\\\": 0.2459, \\\"ppl\\\": 1.32, \\\"N\\\": 5, \\\"T\\\": 10}, \\\"gap_ratio_tg_ours\\\": 15.9, \\\"gap_ratio_base_ours\\\": 1.93, \\\"gap_ratio_tg_dongre\\\": 0.83, \\\"vs_qwen_v7_gap_ratio\\\": 32.1, \\\"baseline_mid_gar\\\": 0.0122}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 1, \\\"done\\\": 3, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 4, \\\"coverage\\\": \\\"3/4\\\", \\\"coverage_pct\\\": 75.0}, \\\"W3\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_014\\\", \\\"claim\\\": \\\"W3\\\", \\\"description\\\": \\\"Downstream task sanity check - simple instruction retention test across turns to link GAR to task performance\\\", \\\"priority\\\": \\\"P2\\\", \\\"gpu_budget_hours\\\": 1, \\\"deps\\\": [\\\"plan_005\\\"], \\\"status\\\": \\\"planned\\\"}], \\\"counts\\\": {\\\"planned\\\": 1, \\\"running\\\": 0, \\\"done\\\": 0, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"0/1\\\", \\\"coverage_pct\\\": 0.0}, \\\"C4, W7\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_015\\\", \\\"claim\\\": \\\"C4, W7\\\", \\\"description\\\": \\\"Statistical significance analysis - paired bootstrap CI from held-out eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically supports 'zero benefit'. Addresses Dream W3 (single seed).\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 0.5, \\\"deps\\\": [\\\"plan_008\\\"], \\\"status\\\": \\\"orphaned\\\", \\\"registry_id\\\": \\\"worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\\\", \\\"result\\\": \\\"PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036], UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero benefit. W7 addressed.\\\"}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 0, \\\"failed\\\": 0, \\\"orphaned\\\": 1}, \\\"total\\\": 1, \\\"coverage\\\": \\\"0/1\\\", \\\"coverage_pct\\\": 0.0}, \\\"W8\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_016\\\", \\\"claim\\\": \\\"W8\\\", \\\"description\\\": \\\"Exposure-bias mitigation test - train ThreadGate v7 with scheduled sampling applied to GAR loss (mix teacher-forced + model-generated contexts). Test whether closing exposure bias gap narrows the 30x training-inference GAR gap. Constructive direction that upgrades paper from pure negative result.\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [\\\"plan_008\\\"], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"phase2_tg_s42_v8_schedsampling\\\", \\\"conclusion\\\": \\\"failed\\\", \\\"metrics\\\": {\\\"killed_at_microstep\\\": 1950, \\\"total_microsteps\\\": 24000, \\\"completion_pct\\\": 8.1, \\\"global_step_approx\\\": 244, \\\"total_global_steps\\\": 3000, \\\"ss_steps_observed\\\": 1, \\\"tf_lgar_mean_step850_1400\\\": 0.0062, \\\"tf_lgar_std\\\": 0.0082, \\\"tf_lgar_collapse_step\\\": 800, \\\"gate_mean_final\\\": 0.93, \\\"ss_ratio_at_kill\\\": 0.081, \\\"crash_reason\\\": \\\"killed by director: SS path code bug (D026) makes experiment invalid, GPU needed for PCGrad\\\", \\\"design_flaw_ss_ramp_too_slow\\\": true, \\\"design_flaw_no_ss_tf_separate_logging\\\": true}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 0, \\\"failed\\\": 1, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"0/1\\\", \\\"coverage_pct\\\": 0.0}, \\\"R4\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_017\\\", \\\"claim\\\": \\\"R4\\\", \\\"description\\\": \\\"Code-paper architecture verification - confirm ThreadGate implementation matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code audit, no GPU.\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 0, \\\"deps\\\": [], \\\"status\\\": \\\"orphaned\\\", \\\"registry_id\\\": \\\"worker_analysis_code_paper_arch_verify_20260519T144058\\\", \\\"result\\\": \\\"CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.\\\"}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 0, \\\"failed\\\": 0, \\\"orphaned\\\": 1}, \\\"total\\\": 1, \\\"coverage\\\": \\\"0/1\\\", \\\"coverage_pct\\\": 0.0}, \\\"C3, W8\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_018\\\", \\\"claim\\\": \\\"C3, W8\\\", \\\"description\\\": \\\"PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for gate params only. If 30x gap persists after removing gradient conflict → causal evidence that exposure bias (not gradient competition) is the root cause.\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [\\\"plan_006\\\"], \\\"registry_id\\\": \\\"phase2_tg_s42_v9_pcgrad\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_iid_ours_mid_gar\\\": 0.5002, \\\"eval_iid_dongre_mid_gar\\\": 0.0123, \\\"eval_iid_ppl\\\": 2.78, \\\"eval_iid_ntp\\\": 0.9752, \\\"eval_heldout_ours_mid_gar\\\": 0.5002, \\\"eval_heldout_dongre_mid_gar\\\": 0.0123, \\\"eval_heldout_ppl\\\": 2.78, \\\"eval_heldout_ntp\\\": 0.9752, \\\"eval_modelgen_ours_mid_gar\\\": 0.0151, \\\"eval_modelgen_dongre_mid_gar\\\": 0.0173, \\\"eval_modelgen_ppl\\\": 1.5, \\\"vs_v7_iid_ppl_diff\\\": 0.004, \\\"vs_v7_iid_gar_diff\\\": -0.0033}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 1, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"1/1\\\", \\\"coverage_pct\\\": 100.0}, \\\"C2, MF5\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_019\\\", \\\"claim\\\": \\\"C2, MF5\\\", \\\"description\\\": \\\"Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen. Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 6, \\\"deps\\\": [\\\"plan_002\\\"], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"v7_tg_s123\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"epoch_1\\\": {\\\"avg_loss\\\": 0.9447, \\\"avg_ntp_loss\\\": 0.9434, \\\"avg_gar_loss\\\": 0.0013, \\\"avg_div_loss\\\": 0}, \\\"epoch_2\\\": {\\\"avg_loss\\\": 0.9315, \\\"avg_ntp_loss\\\": 0.9305, \\\"avg_gar_loss\\\": 0.001, \\\"avg_div_loss\\\": 0}, \\\"final_gate\\\": {\\\"mean\\\": 0.9467, \\\"std\\\": 0.051, \\\"min\\\": 0.793, \\\"max\\\": 1}, \\\"final_gate_profile\\\": {\\\"L0\\\": 0.883, \\\"L1\\\": 0.793, \\\"L2\\\": 0.996, \\\"L3\\\": 0.988, \\\"L4\\\": 0.984, \\\"L5\\\": 0.797, \\\"L6\\\": 0.961, \\\"L7\\\": 0.918, \\\"L8\\\": 0.965, \\\"L9\\\": 0.934, \\\"L10\\\": 0.969, \\\"L11\\\": 0.918, \\\"L12\\\": 0.926, \\\"L13\\\": 0.941, \\\"L14\\\": 0.93, \\\"L15\\\": 0.965, \\\"L16\\\": 0.941, \\\"L17\\\": 0.91, \\\"L18\\\": 0.961, \\\"L19\\\": 0.965, \\\"L20\\\": 0.973, \\\"L21\\\": 0.988, \\\"L22\\\": 0.969, \\\"L23\\\": 0.98, \\\"L24\\\": 0.98, \\\"L25\\\": 0.984, \\\"L26\\\": 0.988, \\\"L27\\\": 1}, \\\"training_time_s\\\": 21425.2}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 1, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"1/1\\\", \\\"coverage_pct\\\": 100.0}, \\\"C4, MF6\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_020\\\", \\\"claim\\\": \\\"C4, MF6\\\", \\\"description\\\": \\\"Expanded eval set — increase from 50 to 200 conversations (idx>=7000 from UltraChat). Boost bootstrap CI statistical power.\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [\\\"plan_008\\\"], \\\"status\\\": \\\"planned\\\"}], \\\"counts\\\": {\\\"planned\\\": 1, \\\"running\\\": 0, \\\"done\\\": 0, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"0/1\\\", \\\"coverage_pct\\\": 0.0}, \\\"C3, SF4\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_022\\\", \\\"claim\\\": \\\"C3, SF4\\\", \\\"description\\\": \\\"λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient competition trend under higher GAR weight. If budget allows, add λ=0.1.\\\", \\\"priority\\\": \\\"P2\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [\\\"plan_002\\\"], \\\"status\\\": \\\"planned\\\"}], \\\"counts\\\": {\\\"planned\\\": 1, \\\"running\\\": 0, \\\"done\\\": 0, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"0/1\\\", \\\"coverage_pct\\\": 0.0}, \\\"W8, C3\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_023\\\", \\\"claim\\\": \\\"W8, C3\\\", \\\"description\\\": \\\"v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0 (match v7). Tests whether training on model-generated text closes the 30x distribution shift gap. If successful, paper upgrades from pure negative to 'diagnosis + initial remedy'. D026.\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [\\\"plan_002\\\"], \\\"status\\\": \\\"DONE\\\", \\\"registry_id\\\": \\\"phase2_tg_s42_v8b_resume\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"training\\\": {\\\"total_steps\\\": 3000, \\\"epochs_completed\\\": 3, \\\"wall_clock_hours\\\": 8.1, \\\"final_loss\\\": 0.933, \\\"final_ntp_loss\\\": 0.9322, \\\"final_gar_loss\\\": 0.0008, \\\"final_gate_mean\\\": 0.9586, \\\"final_gate_std\\\": 0.0582, \\\"ss_ratio\\\": 0.5}, \\\"eval_iid\\\": {\\\"gar_ours\\\": 0.4983, \\\"gar_dongre\\\": 0.3855, \\\"ppl\\\": 2.78}, \\\"eval_modelgen\\\": {\\\"gar_ours\\\": 0.3177, \\\"gar_dongre\\\": 0.3533, \\\"ppl\\\": 1.38}, \\\"vs_v7\\\": {\\\"iid_gar_ours_delta\\\": -0.005, \\\"modelgen_gar_ours_delta\\\": 0.302, \\\"gap_ratio_v7\\\": 32, \\\"gap_ratio_v8b\\\": 1.57}}}], \\\"counts\\\": {\\\"planned\\\": 0, \\\"running\\\": 0, \\\"done\\\": 1, \\\"failed\\\": 0, \\\"orphaned\\\": 0}, \\\"total\\\": 1, \\\"coverage\\\": \\\"1/1\\\", \\\"coverage_pct\\\": 100.0}}, \\\"unassigned\\\": [], \\\"summary\\\": {\\\"total_experiments\\\": 22, \\\"total_claims\\\": 15, \\\"counts\\\": {\\\"planned\\\": 4, \\\"running\\\": 1, \\\"done\\\": 13, \\\"failed\\\": 2, \\\"orphaned\\\": 2}, \\\"coverage\\\": \\\"13/22\\\", \\\"coverage_pct\\\": 59.1, \\\"unassigned\\\": 0}}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"claims\": [\"C1\", \"C2\", \"C2, C4\", \"C2, MF5\", \"C3\", \"C3, SF4\", \"C3, W8\", \"C4\", \"C4, MF6\", \"C4, W7\", \"C5\", \"R4\", \"W3\", \"W8\", \"W8, C3\"], \"matrix\": {\"C1\": {\"experiments\": [{\"id\": \"plan_001\", \"claim\": \"C1\", \"description\": \"Phase 1 GAR degradation diagnosis on Qwen-2.5-7B (70.8% raw drop)\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [], \"registry_id\": \"phase1_gar_diag\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"turn1_avg_gar\": 0.0418, \"mid_turns_avg_gar\": 0.0122, \"relative_drop\": 0.708, \"num_conversations\": 5, \"num_turns\": 10, \"per_turn_avg_gar\": [0.0418, 0.0241, 0.0224, 0.013, 0.0133, 0.0086, 0.0078, 0.008, 0.0157, 0.0064]}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C2\": {\"experiments\": [{\"id\": \"plan_002\", \"claim\": \"C2\", \"description\": \"ThreadGate v7 training (MSE+gate_div) - training GAR 0.48, inference GAR 0.016\", \"priority\": \"P0\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_001\"], \"registry_id\": \"phase2_tg_s42_v7\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_iid_ours_mid_gar\": 0.5035, \"eval_iid_dongre_mid_gar\": 0.0152, \"eval_iid_ppl\": 2.784, \"eval_heldout_ours_mid_gar\": 0.5035, \"eval_heldout_dongre_mid_gar\": 0.0152, \"eval_heldout_ppl\": 2.78, \"eval_modelgen_ours_mid_gar\": 0.0157, \"eval_modelgen_dongre_mid_gar\": 0.0194, \"eval_modelgen_ppl\": 1.36, \"gate_mean_final\": 0.9336, \"gate_std_final\": 0.0492}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C4\": {\"experiments\": [{\"id\": \"plan_003\", \"claim\": \"C4\", \"description\": \"Uniform Gate ablation - isolate turn conditioning contribution\", \"priority\": \"P0\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_001\"], \"registry_id\": \"phase2_ug_s42\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"epoch0_avg_loss\": 1.0019, \"epoch0_avg_ntp\": 0.9755, \"epoch0_avg_gar\": 0.0259, \"epoch0_avg_div\": 0.0005, \"epoch1_avg_loss\": 0.9447, \"epoch1_avg_ntp\": 0.9435, \"epoch1_avg_gar\": 0.0013, \"epoch1_avg_div\": 0, \"epoch2_avg_loss\": 0.9319, \"epoch2_avg_ntp\": 0.9309, \"epoch2_avg_gar\": 0.001, \"epoch2_avg_div\": 0, \"final_gate_mean\": 0.9598, \"final_gate_std\": 0.0518, \"final_gate_min\": 0.7773, \"final_gate_max\": 1, \"final_profile_L3\": 0.777, \"final_profile_L5\": 0.812, \"final_profile_L0\": 0.875, \"final_profile_L27\": 1, \"training_time_seconds\": 21994.5, \"training_time_hours\": 6.1, \"global_steps\": 7950, \"unexpected_per_layer_variation\": true, \"eval_modelgen_ours_mid_gar\": 0.0149, \"eval_modelgen_dongre_mid_gar\": 0.0185, \"eval_modelgen_ppl\": 1.396}}, {\"id\": \"plan_004\", \"claim\": \"C4\", \"description\": \"LoRA-only ablation - isolate gating mechanism contribution\", \"priority\": \"P0\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_001\"], \"registry_id\": \"phase2_lora_only_s42\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"epochs_completed\": 3, \"global_steps\": 3000, \"training_time_seconds\": 20588.6, \"training_time_hours\": 5.7, \"gate_fixed\": 1, \"gate_type_actual\": \"none\", \"final_lora_size_mb\": 20, \"eval_modelgen_ours_mid_gar\": 0.0245, \"eval_modelgen_dongre_mid_gar\": 0.0185, \"eval_modelgen_ppl\": 1.371}}, {\"id\": \"plan_005\", \"claim\": \"C4\", \"description\": \"Four-way eval (Base/TG/UG/LoRA-only x GAR-ours/Dongre + PPL)\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_002\", \"plan_003\", \"plan_004\"], \"registry_id\": \"phase2_4way_eval\", \"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"base_ours_mid_gar\": 0.0107, \"base_ours_recovery_pp\": -0.15, \"base_dongre_mid_gar\": 0.003, \"base_dongre_recovery_pp\": -0.92, \"base_ppl\": 4.23, \"base_ntp\": 1.4162, \"tg_ours_mid_gar\": 0.4866, \"tg_ours_recovery_pp\": 47.44, \"tg_dongre_mid_gar\": 0.0157, \"tg_dongre_recovery_pp\": 0.35, \"tg_ppl\": 2.63, \"tg_ntp\": 0.9484, \"ug_ours_mid_gar\": 0.4923, \"ug_ours_recovery_pp\": 48.01, \"ug_dongre_mid_gar\": 0.013, \"ug_dongre_recovery_pp\": 0.08, \"ug_ppl\": 2.62, \"ug_ntp\": 0.9433, \"lora_ours_mid_gar\": 0.486, \"lora_ours_recovery_pp\": 47.39, \"lora_dongre_mid_gar\": 0.0137, \"lora_dongre_recovery_pp\": 0.15, \"lora_ppl\": 2.63, \"lora_ntp\": 0.9482, \"route_b_confirmed\": true, \"gating_incremental_benefit\": \"none\"}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 2, \"failed\": 1, \"orphaned\": 0}, \"total\": 3, \"coverage\": \"2/3\", \"coverage_pct\": 66.7}, \"C3\": {\"experiments\": [{\"id\": \"plan_006\", \"claim\": \"C3\", \"description\": \"Gradient conflict analysis on v7 (3 epoch checkpoints) - NTP vs GAR gradient cos_sim + magnitude ratio\", \"priority\": \"P0\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_002\"], \"registry_id\": \"analysis_gradient_conflict\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"epoch0_cos_sim\": -0.089, \"epoch1_cos_sim\": -0.054, \"epoch2_cos_sim\": -0.042, \"epoch0_neg_layers_pct\": 78.6, \"epoch1_neg_layers_pct\": 71.4, \"epoch2_neg_layers_pct\": 67.9, \"epoch0_mag_ratio\": 7.5, \"epoch1_mag_ratio\": 13.7, \"epoch2_mag_ratio\": 14.7}}, {\"id\": \"plan_007\", \"claim\": \"C3\", \"description\": \"Attention heatmap visualization (4 models x 3 conversations x 28 layers)\", \"priority\": \"P0\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_002\", \"plan_003\", \"plan_004\"], \"registry_id\": \"analysis_attention_heatmap\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"base_mean_goal_attn\": 0.0136, \"base_decay\": 0.875, \"tg_mean_goal_attn\": 0.0232, \"tg_decay\": 0.777, \"ug_mean_goal_attn\": 0.0216, \"ug_decay\": 0.803, \"lora_mean_goal_attn\": 0.0216, \"lora_decay\": 0.81, \"gating_incremental_benefit\": \"none\"}}, {\"id\": \"plan_013\", \"claim\": \"C3\", \"description\": \"Llama-3.1-8B gradient conflict analysis - verify NTP-GAR competition is model-agnostic\", \"priority\": \"P1\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_010\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 2, \"failed\": 0, \"orphaned\": 0}, \"total\": 3, \"coverage\": \"2/3\", \"coverage_pct\": 66.7}, \"C2, C4\": {\"experiments\": [{\"id\": \"plan_008\", \"claim\": \"C2, C4\", \"description\": \"Held-out eval: create truly held-out eval set (50 convs, idx>=8000 from UltraChat full) and re-run 4-way eval to validate conclusions on unseen data\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_005\"], \"status\": \"DONE\", \"registry_id\": \"phase2_4way_eval_heldout\", \"conclusion\": \"success\", \"metrics\": {\"base_ours_mid_gar\": 0.0128, \"base_ours_recovery_pp\": 0.06, \"base_dongre_mid_gar\": 0.0031, \"base_dongre_recovery_pp\": -0.91, \"base_ppl\": 4.34, \"base_ntp\": 1.4045, \"tg_ours_mid_gar\": 0.5035, \"tg_ours_recovery_pp\": 49.13, \"tg_dongre_mid_gar\": 0.0152, \"tg_dongre_recovery_pp\": 0.3, \"tg_ppl\": 2.78, \"tg_ntp\": 0.9771, \"ug_ours_mid_gar\": 0.5053, \"ug_ours_recovery_pp\": 49.31, \"ug_dongre_mid_gar\": 0.0124, \"ug_dongre_recovery_pp\": 0.02, \"ug_ppl\": 2.78, \"ug_ntp\": 0.9752, \"lora_ours_mid_gar\": 0.4978, \"lora_ours_recovery_pp\": 48.56, \"lora_dongre_mid_gar\": 0.0132, \"lora_dongre_recovery_pp\": 0.1, \"lora_ppl\": 2.78, \"lora_ntp\": 0.9771, \"three_way_convergence_confirmed\": true, \"gar_ours_spread_pp\": 0.75, \"ppl_spread\": 0, \"data_overlap\": false}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C5\": {\"experiments\": [{\"id\": \"plan_009\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B Phase 1 GAR degradation diagnosis - confirm GAR decay exists on different architecture\", \"priority\": \"P0\", \"gpu_budget_hours\": 0.5, \"deps\": [], \"status\": \"DONE\", \"registry_id\": \"llama_phase1_gar_diag\", \"conclusion\": \"success\", \"metrics\": {\"per_turn_gar\": {\"turn_1\": 0.0263, \"turn_2\": 0.0183, \"turn_3\": 0.0087, \"turn_4\": 0.0055, \"turn_5\": 0.006, \"turn_6\": 0.0035, \"turn_7\": 0.0038, \"turn_8\": 0.0037, \"turn_9\": 0.005, \"turn_10\": 0.0026}, \"t1_t10_decay_pct\": 90.1, \"t1_mid38_drop_pct\": 80.2, \"n_topics\": 5, \"model\": \"Meta-Llama-3.1-8B-Instruct\", \"mode\": \"gen\", \"n_conversations\": 5, \"n_turns\": 10}}, {\"id\": \"plan_010\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B ThreadGate v7 training - replicate Qwen setup on Llama\", \"priority\": \"P0\", \"gpu_budget_hours\": 7, \"deps\": [\"plan_009\"], \"status\": \"DONE\", \"registry_id\": \"llama_tg_s42\", \"conclusion\": \"success\", \"metrics\": {\"epochs_completed\": 3, \"total_steps\": 3000, \"wall_clock_seconds\": 26212, \"wall_clock_hours\": 7.28, \"final_avg_loss\": 0.9233, \"final_avg_ntp\": 0.9224, \"final_avg_gar\": 0.0009, \"final_avg_div\": 0, \"final_gate_mean\": 0.9099, \"final_gate_std\": 0.0701, \"final_gate_min\": 0.7188, \"final_gate_max\": 0.9922, \"gate_profile_step3000\": {\"L0\": 0.957, \"L1\": 0.973, \"L2\": 0.977, \"L3\": 0.965, \"L4\": 0.992, \"L5\": 0.969, \"L6\": 0.957, \"L7\": 0.957, \"L8\": 0.961, \"L9\": 0.949, \"L10\": 0.938, \"L11\": 0.934, \"L12\": 0.969, \"L13\": 0.953, \"L14\": 0.957, \"L15\": 0.965, \"L16\": 0.953, \"L17\": 0.961, \"L18\": 0.922, \"L19\": 0.902, \"L20\": 0.883, \"L21\": 0.863, \"L22\": 0.836, \"L23\": 0.844, \"L24\": 0.809, \"L25\": 0.719, \"L26\": 0.762, \"L27\": 0.805, \"L28\": 0.801, \"L29\": 0.855, \"L30\": 0.898, \"L31\": 0.934}, \"checkpoint_size_gate_mb\": 4.2, \"checkpoint_size_lora_mb\": 26, \"gpu\": \"NVIDIA RTX PRO 6000 Blackwell\", \"vram_gb\": 102, \"mem_used_gb\": 63.4}}, {\"id\": \"plan_011\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B LoRA-only training - cross-model gating redundancy validation (D020)\", \"priority\": \"P0\", \"gpu_budget_hours\": 7, \"deps\": [\"plan_009\"], \"status\": \"RUNNING\", \"registry_id\": \"llama_lora_only_s42\"}, {\"id\": \"plan_012\", \"claim\": \"C5\", \"description\": \"Llama-3.1-8B 3-way eval (Base/TG/LoRA-only x GAR + PPL) on held-out data\", \"priority\": \"P0\", \"gpu_budget_hours\": 1, \"deps\": [\"plan_010\", \"plan_011\"], \"status\": \"DONE\", \"registry_id\": \"llama_eval_s42\", \"conclusion\": \"success\", \"metrics\": {\"tf_base\": {\"gar_ours\": 0.0166, \"ngar_ours\": 0.3882, \"gar_dongre\": 0.0038, \"ngar_dongre\": 0.163, \"ppl\": 3.45, \"N\": 50, \"T\": 4}, \"tf_tg\": {\"gar_ours\": 0.4836, \"ngar_ours\": 11.8818, \"gar_dongre\": 0.018, \"ngar_dongre\": 0.7922, \"ppl\": 2.57, \"N\": 50, \"T\": 4}, \"ar_base\": {\"gar_ours\": 0.0086, \"ngar_ours\": 0.0798, \"gar_dongre\": 0.0118, \"ngar_dongre\": 0.1265, \"ppl\": 1.24, \"N\": 5, \"T\": 10}, \"ar_tg\": {\"gar_ours\": 0.0304, \"ngar_ours\": 0.2632, \"gar_dongre\": 0.0217, \"ngar_dongre\": 0.2459, \"ppl\": 1.32, \"N\": 5, \"T\": 10}, \"gap_ratio_tg_ours\": 15.9, \"gap_ratio_base_ours\": 1.93, \"gap_ratio_tg_dongre\": 0.83, \"vs_qwen_v7_gap_ratio\": 32.1, \"baseline_mid_gar\": 0.0122}}], \"counts\": {\"planned\": 0, \"running\": 1, \"done\": 3, \"failed\": 0, \"orphaned\": 0}, \"total\": 4, \"coverage\": \"3/4\", \"coverage_pct\": 75.0}, \"W3\": {\"experiments\": [{\"id\": \"plan_014\", \"claim\": \"W3\", \"description\": \"Downstream task sanity check - simple instruction retention test across turns to link GAR to task performance\", \"priority\": \"P2\", \"gpu_budget_hours\": 1, \"deps\": [\"plan_005\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"C4, W7\": {\"experiments\": [{\"id\": \"plan_015\", \"claim\": \"C4, W7\", \"description\": \"Statistical significance analysis - paired bootstrap CI from held-out eval (50 convs) for TG-LoRA-only comparison. If CI includes 0 → statistically supports 'zero benefit'. Addresses Dream W3 (single seed).\", \"priority\": \"P1\", \"gpu_budget_hours\": 0.5, \"deps\": [\"plan_008\"], \"status\": \"orphaned\", \"registry_id\": \"worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212\", \"result\": \"PASS: All GAR-ours and PPL 95% CIs include 0 (TG-LO GAR: [-0.0018,+0.0036], UG-LO: [-0.0006,+0.0045], TG-UG: [-0.0030,+0.0006]). Statistically confirms zero benefit. W7 addressed.\"}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 1}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"W8\": {\"experiments\": [{\"id\": \"plan_016\", \"claim\": \"W8\", \"description\": \"Exposure-bias mitigation test - train ThreadGate v7 with scheduled sampling applied to GAR loss (mix teacher-forced + model-generated contexts). Test whether closing exposure bias gap narrows the 30x training-inference GAR gap. Constructive direction that upgrades paper from pure negative result.\", \"priority\": \"P1\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_008\"], \"status\": \"DONE\", \"registry_id\": \"phase2_tg_s42_v8_schedsampling\", \"conclusion\": \"failed\", \"metrics\": {\"killed_at_microstep\": 1950, \"total_microsteps\": 24000, \"completion_pct\": 8.1, \"global_step_approx\": 244, \"total_global_steps\": 3000, \"ss_steps_observed\": 1, \"tf_lgar_mean_step850_1400\": 0.0062, \"tf_lgar_std\": 0.0082, \"tf_lgar_collapse_step\": 800, \"gate_mean_final\": 0.93, \"ss_ratio_at_kill\": 0.081, \"crash_reason\": \"killed by director: SS path code bug (D026) makes experiment invalid, GPU needed for PCGrad\", \"design_flaw_ss_ramp_too_slow\": true, \"design_flaw_no_ss_tf_separate_logging\": true}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 0, \"failed\": 1, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"R4\": {\"experiments\": [{\"id\": \"plan_017\", \"claim\": \"R4\", \"description\": \"Code-paper architecture verification - confirm ThreadGate implementation matches paper Eq.3 (gate on residual vs gate on sub-layer output). Quick code audit, no GPU.\", \"priority\": \"P0\", \"gpu_budget_hours\": 0, \"deps\": [], \"status\": \"orphaned\", \"registry_id\": \"worker_analysis_code_paper_arch_verify_20260519T144058\", \"result\": \"CRITICAL: code implements x+g·f(x) (ReZero-style), dream paper.tex wrote g·x+f(x). Semantically opposite when g→0. Data unaffected. D023.\"}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 1}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"C3, W8\": {\"experiments\": [{\"id\": \"plan_018\", \"claim\": \"C3, W8\", \"description\": \"PCGrad baseline - project NTP gradient onto GAR-orthogonal plane for gate params only. If 30x gap persists after removing gradient conflict → causal evidence that exposure bias (not gradient competition) is the root cause.\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_006\"], \"registry_id\": \"phase2_tg_s42_v9_pcgrad\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_iid_ours_mid_gar\": 0.5002, \"eval_iid_dongre_mid_gar\": 0.0123, \"eval_iid_ppl\": 2.78, \"eval_iid_ntp\": 0.9752, \"eval_heldout_ours_mid_gar\": 0.5002, \"eval_heldout_dongre_mid_gar\": 0.0123, \"eval_heldout_ppl\": 2.78, \"eval_heldout_ntp\": 0.9752, \"eval_modelgen_ours_mid_gar\": 0.0151, \"eval_modelgen_dongre_mid_gar\": 0.0173, \"eval_modelgen_ppl\": 1.5, \"vs_v7_iid_ppl_diff\": 0.004, \"vs_v7_iid_gar_diff\": -0.0033}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C2, MF5\": {\"experiments\": [{\"id\": \"plan_019\", \"claim\": \"C2, MF5\", \"description\": \"Multi-seed validation — train TG v7 + LoRA-only with seed=123 on Qwen. Provide mean±std for 30x gap. 1 extra seed sufficient given extreme effect size.\", \"priority\": \"P1\", \"gpu_budget_hours\": 6, \"deps\": [\"plan_002\"], \"status\": \"DONE\", \"registry_id\": \"v7_tg_s123\", \"conclusion\": \"success\", \"metrics\": {\"epoch_1\": {\"avg_loss\": 0.9447, \"avg_ntp_loss\": 0.9434, \"avg_gar_loss\": 0.0013, \"avg_div_loss\": 0}, \"epoch_2\": {\"avg_loss\": 0.9315, \"avg_ntp_loss\": 0.9305, \"avg_gar_loss\": 0.001, \"avg_div_loss\": 0}, \"final_gate\": {\"mean\": 0.9467, \"std\": 0.051, \"min\": 0.793, \"max\": 1}, \"final_gate_profile\": {\"L0\": 0.883, \"L1\": 0.793, \"L2\": 0.996, \"L3\": 0.988, \"L4\": 0.984, \"L5\": 0.797, \"L6\": 0.961, \"L7\": 0.918, \"L8\": 0.965, \"L9\": 0.934, \"L10\": 0.969, \"L11\": 0.918, \"L12\": 0.926, \"L13\": 0.941, \"L14\": 0.93, \"L15\": 0.965, \"L16\": 0.941, \"L17\": 0.91, \"L18\": 0.961, \"L19\": 0.965, \"L20\": 0.973, \"L21\": 0.988, \"L22\": 0.969, \"L23\": 0.98, \"L24\": 0.98, \"L25\": 0.984, \"L26\": 0.988, \"L27\": 1}, \"training_time_s\": 21425.2}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}, \"C4, MF6\": {\"experiments\": [{\"id\": \"plan_020\", \"claim\": \"C4, MF6\", \"description\": \"Expanded eval set — increase from 50 to 200 conversations (idx>=7000 from UltraChat). Boost bootstrap CI statistical power.\", \"priority\": \"P1\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_008\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"C3, SF4\": {\"experiments\": [{\"id\": \"plan_022\", \"claim\": \"C3, SF4\", \"description\": \"λ_GAR sensitivity — train v7 with λ_GAR=10 (1 epoch only). Show gradient competition trend under higher GAR weight. If budget allows, add λ=0.1.\", \"priority\": \"P2\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_002\"], \"status\": \"planned\"}], \"counts\": {\"planned\": 1, \"running\": 0, \"done\": 0, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"0/1\", \"coverage_pct\": 0.0}, \"W8, C3\": {\"experiments\": [{\"id\": \"plan_023\", \"claim\": \"W8, C3\", \"description\": \"v8b: Fixed Scheduled Sampling — fix compute_gar_loss len==1 bug (Option A: handle single-turn mse_target), fix OOM (reduce batch/gen_length), use lambda_gar=1.0 (match v7). Tests whether training on model-generated text closes the 30x distribution shift gap. If successful, paper upgrades from pure negative to 'diagnosis + initial remedy'. D026.\", \"priority\": \"P1\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_002\"], \"status\": \"DONE\", \"registry_id\": \"phase2_tg_s42_v8b_resume\", \"conclusion\": \"success\", \"metrics\": {\"training\": {\"total_steps\": 3000, \"epochs_completed\": 3, \"wall_clock_hours\": 8.1, \"final_loss\": 0.933, \"final_ntp_loss\": 0.9322, \"final_gar_loss\": 0.0008, \"final_gate_mean\": 0.9586, \"final_gate_std\": 0.0582, \"ss_ratio\": 0.5}, \"eval_iid\": {\"gar_ours\": 0.4983, \"gar_dongre\": 0.3855, \"ppl\": 2.78}, \"eval_modelgen\": {\"gar_ours\": 0.3177, \"gar_dongre\": 0.3533, \"ppl\": 1.38}, \"vs_v7\": {\"iid_gar_ours_delta\": -0.005, \"modelgen_gar_ours_delta\": 0.302, \"gap_ratio_v7\": 32, \"gap_ratio_v8b\": 1.57}}}], \"counts\": {\"planned\": 0, \"running\": 0, \"done\": 1, \"failed\": 0, \"orphaned\": 0}, \"total\": 1, \"coverage\": \"1/1\", \"coverage_pct\": 100.0}}, \"unassigned\": [], \"summary\": {\"total_experiments\": 22, \"total_claims\": 15, \"counts\": {\"planned\": 4, \"running\": 1, \"done\": 13, \"failed\": 2, \"orphaned\": 2}, \"coverage\": \"13/22\", \"coverage_pct\": 59.1, \"unassigned\": 0}}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "b0972125-9277-49a5-8881-4ce0084752a6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 54_

```json
{
  "type": "last-prompt",
  "leafUuid": "cb8b0eca-9670-43bd-b832-e2b353e6873f",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Runtime record

_source line 55_

```json
{
  "type": "ai-title",
  "aiTitle": "Sync experiment_plan.yaml with registry mappings",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Assistant

_source line 56 · 2026-05-22T04:56:02.272Z_

<details><summary>Logged reasoning block</summary>

```text
The coverage matrix looks good. Let me summarize the results:

Key observations:
1. plan_009 → llama_phase1_gar_diag: now shows DONE/success ✓
2. plan_010 → llama_tg_s42: now shows DONE/success ✓
3. plan_012 → llama_eval_s42: now shows DONE/success ✓
4. plan_019 → v7_tg_s123: now shows DONE/success ✓
5. plan_023 → phase2_tg_s42_v8b_resume: now shows DONE/success ✓


6. plan_015 and plan_017 are showing as orphaned with worker_analysis registry entries that have a different format, though they both have `status: done` set, so I need to verify if they need updating.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cb8b0eca-9670-43bd-b832-e2b353e6873f",
  "isSidechain": false,
  "requestId": "req_011CbH1foMAHrE5Pvax3no3a",
  "type": "assistant",
  "uuid": "6b48783c-e13d-4bad-a012-ce85633cf7f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AXjYJ3xwkYWFKttVRnP7Kd",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8997,
      "cache_read_input_tokens": 35108,
      "output_tokens": 560,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8997,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 560,
          "cache_read_input_tokens": 35108,
          "cache_creation_input_tokens": 8997,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8997
          },
          "type": "message"
        }
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

_source line 57 · 2026-05-22T04:56:02.685Z_

Coverage matrix is working. Two orphaned entries remain: plan_015 and plan_017. Let me check their registry entries.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6b48783c-e13d-4bad-a012-ce85633cf7f1",
  "isSidechain": false,
  "requestId": "req_011CbH1foMAHrE5Pvax3no3a",
  "type": "assistant",
  "uuid": "a23c584a-2a43-47af-a3f1-63a5d59c3b7b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AXjYJ3xwkYWFKttVRnP7Kd",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8997,
      "cache_read_input_tokens": 35108,
      "output_tokens": 560,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8997,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 560,
          "cache_read_input_tokens": 35108,
          "cache_creation_input_tokens": 8997,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8997
          },
          "type": "message"
        }
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

_source line 58 · 2026-05-22T04:56:05.272Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01EnrG6xXqy1umLWFbm4SsjA`</summary>

```json
{
  "pattern": "worker_analysis_bootstrap_ci_tg_vs_lora_20260519T144212|worker_analysis_code_paper_arch_verify_20260519T144058",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/registry.yaml",
  "output_mode": "content",
  "-C": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a23c584a-2a43-47af-a3f1-63a5d59c3b7b",
  "isSidechain": false,
  "requestId": "req_011CbH1foMAHrE5Pvax3no3a",
  "type": "assistant",
  "uuid": "8b0e08ec-5055-4b4b-9f61-ee67e1db57fd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AXjYJ3xwkYWFKttVRnP7Kd",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8997,
      "cache_read_input_tokens": 35108,
      "output_tokens": 560,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8997,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 560,
          "cache_read_input_tokens": 35108,
          "cache_creation_input_tokens": 8997,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8997
          },
          "type": "message"
        }
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

_source line 59 · 2026-05-22T04:56:05.303Z_

<details><summary>↩ Tool result · `toolu_01EnrG6xXqy1umLWFbm4SsjA`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8b0e08ec-5055-4b4b-9f61-ee67e1db57fd",
  "isSidechain": false,
  "promptId": "12d84496-ea41-4694-80bf-f7248a3f7ab7",
  "type": "user",
  "uuid": "d6885cc1-ee99-4a16-8d6a-4cf7c882a838",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "8b0e08ec-5055-4b4b-9f61-ee67e1db57fd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 60 · 2026-05-22T04:56:13.581Z_

These registry IDs don't exist in registry.yaml — that's why they show as orphaned. The plan entries have `status: done` with results inline, but point to non-existent registry entries. Since the task says not to modify fields other than `registry_id`, and these registry IDs simply don't exist in the registry, there's nothing to fix here — they're correctly identified as orphaned because their registry entries were never created.

**Summary of changes made:**

| Plan | Change |
|------|--------|
| plan_009 | Added `registry_id: llama_phase1_gar_diag` → now resolves to DONE/success |
| plan_010 | Added `registry_id: llama_tg_s42` → now resolves to DONE/success |
| plan_012 | Added `registry_id: llama_eval_s42` → now resolves to DONE/success |
| plan_019 | Added `registry_id: v7_tg_s123` → now resolves to DONE/success |
| plan_023 | Changed `phase2_tg_s42_v8b_ss_fixed` → `phase2_tg_s42_v8b_resume` → now resolves to DONE/success |

**Coverage improved from ~50% to 59.1% (13/22 done).** Remaining gaps: 4 planned, 1 running, 2 failed, 2 orphaned (plan_015/017 — their `worker_analysis_*` registry IDs don't exist in registry.yaml).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d6885cc1-ee99-4a16-8d6a-4cf7c882a838",
  "isSidechain": false,
  "requestId": "req_011CbH1gpm1kf1RhsLsVQDNW",
  "type": "assistant",
  "uuid": "e0f2094e-016f-48d0-b8e5-02318b59d611",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Mf9v37ZwzQwAf8n1Mf794f",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 574,
      "cache_read_input_tokens": 44105,
      "output_tokens": 372,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 574,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 372,
          "cache_read_input_tokens": 44105,
          "cache_creation_input_tokens": 574,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 574
          },
          "type": "message"
        }
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
  "leafUuid": "e0f2094e-016f-48d0-b8e5-02318b59d611",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

### Runtime record

_source line 62_

```json
{
  "type": "ai-title",
  "aiTitle": "Sync experiment_plan.yaml with registry mappings",
  "sessionId": "1e07ddf8-2b04-46c0-950a-a39a0e6c1fe3"
}
```

---

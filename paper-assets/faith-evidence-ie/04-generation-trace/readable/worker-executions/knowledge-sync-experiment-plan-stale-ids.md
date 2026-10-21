# knowledge sync experiment plan stale ids

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 34
- **Recorded user turns:** 0
- **Tool calls:** 11
- **Original source:** `logs/workers/worker_knowledge_sync_experiment_plan_stale_ids_20260519T054353.log`
- **Structured JSON:** [`d1136da7d80aa2e38039.json`](../../sessions/d1/d1136da7d80aa2e38039.json)

## Before a recorded user message

34 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### System

_source line 2_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "tools": [
    "Task",
    "AskUserQuestion",
    "Bash",
    "CronCreate",
    "CronDelete",
    "CronList",
    "Edit",
    "EnterPlanMode",
    "EnterWorktree",
    "ExitPlanMode",
    "ExitWorktree",
    "Glob",
    "Grep",
    "ListMcpResourcesTool",
    "Monitor",
    "NotebookEdit",
    "PushNotification",
    "Read",
    "ReadMcpResourceTool",
    "RemoteTrigger",
    "ScheduleWakeup",
    "Skill",
    "TaskOutput",
    "TaskStop",
    "TodoWrite",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "Write",
    "mcp__agent-ml-research__append_idea",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__update_registry"
  ],
  "mcp_servers": [
    {
      "name": "agent-ml-research",
      "status": "connected"
    }
  ],
  "model": "claude-opus-4-6",
  "permissionMode": "bypassPermissions",
  "slash_commands": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api",
    "clear",
    "compact",
    "context",
    "heapdump",
    "init",
    "review",
    "security-review",
    "extra-usage",
    "usage",
    "insights",
    "team-onboarding"
  ],
  "apiKeySource": "none",
  "claude_code_version": "2.1.126",
  "output_style": "default",
  "agents": [
    "claude",
    "Explore",
    "general-purpose",
    "Plan",
    "statusline-setup"
  ],
  "skills": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api"
  ],
  "plugins": [],
  "analytics_disabled": false,
  "uuid": "1834d570-1637-4c81-8d4e-6378422d8e07",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Runtime record

_source line 3_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1779174000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "d7834e26-4c82-425f-b0b4-3aee754ab1cd",
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4"
}
```

---

### Assistant

_source line 4_

我来读取 experiment_plan.yaml 和 registry，然后对照同步。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "5d14dc2d-9f79-46c8-8180-ed172b7e7df9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GcTU5qBcTgjmZWDGthW6AD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13930,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13930
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 5_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_018NYGxdsQdZzpDKqnSEnmJj`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "cead923c-1355-40bc-988e-3bbc00cc32d5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GcTU5qBcTgjmZWDGthW6AD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13930,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13930
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-19T05:44:05.129Z_

<details><summary>↩ Tool result · `toolu_018NYGxdsQdZzpDKqnSEnmJj`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "0b3816e7-5d0b-4a9d-9b94-c47bbba00a73",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Now let me read both the experiment_plan.yaml and the registry in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "fa229600-f679-47a3-a31f-4701418535fe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011myR6xPT3Lpbgd6yALf1tB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 806,
      "cache_read_input_tokens": 25377,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 806
      },
      "output_tokens": 23,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01CdNShZdV5d11nMZgdLw9Me`</summary>

```json
{
  "project": "faith-evidence-ie",
  "file": "experiment_plan.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "bbad8b72-3616-4c59-b474-2ac0a8e0586d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011myR6xPT3Lpbgd6yALf1tB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 806,
      "cache_read_input_tokens": 25377,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 806
      },
      "output_tokens": 23,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-19T05:44:09.323Z_

<details><summary>↩ Tool result · `toolu_01CdNShZdV5d11nMZgdLw9Me`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'mistakes.yaml', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'experiment_plan.yaml'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "7955fe5d-9f4f-42bd-9bb6-e0dec7027520",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'mistakes.yaml', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'experiment_plan.yaml'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'mistakes.yaml', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'experiment_plan.yaml'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01UKhBf9ZzfmDkWYfqZNB2Zu`</summary>

```json
{
  "project": "faith-evidence-ie",
  "limit": 0,
  "fields": [
    "status",
    "conclusion",
    "hypothesis",
    "exp_id"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "536a0633-f288-4be6-acc5-12f100f110dc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011myR6xPT3Lpbgd6yALf1tB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 806,
      "cache_read_input_tokens": 25377,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 806
      },
      "output_tokens": 23,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-19T05:44:10.861Z_

<details><summary>↩ Tool result · `toolu_01UKhBf9ZzfmDkWYfqZNB2Zu`</summary>

```text
&lt;persisted-output>
Output too large (53.4KB). Full output saved to: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/634a5108-09f6-4d84-84f8-5d5a864789c4/tool-results/toolu_01UKhBf9ZzfmDkWYfqZNB2Zu.txt

Preview (first 2KB):
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_s44_r2\": {\"status\": \"RUNNING\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\"}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"RUNNING\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"success\"}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"failed\"}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"failed\"}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_train\": {\"status\": \"RUNNING\", \"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\"}, \"plan017_14b_sft\": {\"status\": \"RUNNING\"}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "995ea420-65ff-4ede-97bb-a18c93d3c595",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan019_1_7b_rsft_s44_r2\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\"}, \\\"plan019_1_7b_rsft_s43_r2\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan019_1_7b_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan019_8b_rsft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_ced_score\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_train\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\\\"}, \\\"plan017_14b_sft\\\": {\\\"status\\\": \\\"RUNNING\\\"}, \\\"d111_4b_sft_s42_reeval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan019_8b_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_8b_sft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"grpo_bf16_g4_ckpt200_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"random_rsft_k1_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s44_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s43_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_8b_sft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_grpo_bf16_g4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"random_rsft_k1_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"grpo_bf16_g4_ckpt100_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"wave1_sft_4b_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"wave1_sft_4b_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT 4B seed43 eval (D076 protocol): baseline SFT performance for seed43. Paired with s44 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"seed_llama_rsft_k1_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT baseline for Qwen3-4B seed44: second seed for SFT baseline. Paired with seed43 for mean±std reporting. Expected rel_f1 similar to seed43 (~50.5±1pp).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT baseline for Qwen3-4B seed43: standard SFT without CED filtering. Paired with RSFT to measure CED filtering gain. Expected rel_f1 ~50.5 based on prior 8B SFT results scaled down.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_llama_rsft_k1_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"seed_llama_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_llama_k1_s43_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_8b_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3018 samples vs 9041），预期 rel_f1 与 k=3 相当或略有变化，验证 k=1 在 8B 上同样有效。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_llama_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_1_7b_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：1.7B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3021 samples vs 9042），在最小模型上验证 k=1 RSFT 效果。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"seed_comparison_prep\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan006_1_7b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"rsft_s43_dev_eval_preds\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval RSFT-s43 (CED-scored) on DocRED dev with predictions saved. Prerequisite for Lead 1 CED evidence filtering: per-sentence NLI scoring requires full prediction outputs.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate 1.7B RSFT model (checkpoint-1698) on DocRED dev. Retry after disk-full crash. Validates CED-filtered RSFT at smallest model scale in scaling study.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_r3_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with CED-scored data (9041 samples) on Qwen3-8B, resume from checkpoint-750 after disk-full crash. At 8B scale, CED-filtered RSFT should achieve highest absolute performance in scaling study.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_seed43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate 1.7B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5219. If seed 43 gives similar result (±1pp, i.e., 0.51-0.53), the 1.7B scaling study datapoint is robust.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_test\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Generate 1.7B RSFT test set predictions for CodaLab submission. 1.7B RSFT dev rel_f1=0.5219, expect similar performance on test.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_test\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Generate 8B RSFT test set predictions for CodaLab submission. 8B RSFT dev rel_f1=0.5606, expect similar performance on test.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_seed43_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust against seed variance.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_test\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_seed43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed variance.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_seed43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"lead2_ckpt20_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate GRPO checkpoint-20 from RSFT base (lead2_rsft_grpo_ced_r2) on DocRED dev. If RSFT→GRPO preserves/improves rel_f1 over RSFT baseline (0.4601), it validates the RSFT→GRPO training pipeline as viable.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate Qwen3-8B RSFT (CED-scored data, 9041 samples) on DocRED dev. At 8B scale with near-zero evidence tax, CED-RSFT should achieve highest absolute Ign-F1 in the scaling study.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_seed43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with seed 43 on Qwen3-1.7B will produce comparable performance to other seeds, validating seed robustness for the scaling study\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"post_hoc_bm25_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Post-hoc BM25 evidence retrieval on SFT-no-evidence predictions: if retrieving evidence after RE produces comparable joint Evi-F1 and EDCR to jointly trained RSFT, then joint generation is unnecessary. Expect RSFT to have better evidence quality (lower EDCR) due to training-time evidence grounding.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"lead1_ced_evidence_filter\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"hypothesis\\\": \\\"Post-hoc CED-based evidence filtering on RSFT predictions: removing low-NLI-score evidence sentences at inference time should improve Evi-F1 and EDCR by eliminating distractor citations, without affecting rel_f1.\\\"}, \\\"plan_006_qwen3_8b_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with CED-scored data (9041 samples) on Qwen3-8B will improve rel_f1 over SFT baseline. At 8B scale with near-zero evidence tax, CED-filtered RSFT should achieve the highest absolute performance in the model scaling study.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate 1.7B RSFT model on DocRED dev to measure rel_f1 improvement over SFT baseline. Validates that CED-filtered RSFT generalizes to smallest model scale (1.7B) in the scaling study.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_s44_dev_eval_preds\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-run RSFT s44 dev eval with predictions saved, as prerequisite for CED evidence filtering experiment (线索1: inference-time distractor citation removal). Predictions needed for per-sentence NLI scoring.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"lead2_rsft_grpo_ced_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT→bf16 GRPO two-stage (retry with --data_dir fix): starting from merged RSFT-s43 checkpoint (rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should improve evidence quality (EDCR) while preserving rel_f1.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_train_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues seen in r1/r2 attempts\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"lead2_rsft_grpo_ced\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT→bf16 GRPO two-stage: starting from RSFT best checkpoint (s43, rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should further improve evidence quality (EDCR) while preserving rel_f1, because RSFT provides stable base preventing catastrophic forgetting seen in SFT→GRPO.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_8b_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring on Qwen3-8B RSFT candidates (24216 gens from 3027 docs) will produce high-quality filtered training data. At 8B scale with near-zero evidence tax, CED-filtered RSFT should yield further gains over an already strong SFT baseline.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with CED-scored data on Qwen3-1.7B will improve relation extraction F1 over SFT baseline by selectively reinforcing high-quality extraction patterns, similar to gains seen on 4B model\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_002_test_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT-CED s44 (best dev config, rel_f1=0.4655) maintains improvement over SFT on held-out test set, confirming CED-filtered rejection sampling gains are not dev-set overfitting. Test Ign-F1 should exceed SFT test baseline.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_candidates_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Resuming 8B candidate generation from idx 2701 will complete the full RSFT candidate set needed for reward-based filtering and RSFT training\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_016_llama_rsft_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families (Qwen→LLaMA).\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring (NLI contrastive discrimination) can effectively filter 1.7B model candidates despite lower generation quality: NLI-based selection should identify high-quality evidence samples even from a capacity-limited generator.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_007_redocred_rsft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"hypothesis\\\": \\\"CED-RSFT improvements on DocRED should transfer to Re-DocRED: RSFT model should outperform SFT baseline on Re-DocRED Ign-F1, demonstrating cross-dataset generalization of rejection sampling gains.\\\"}, \\\"plan_006_qwen3_1_7b_rsft_candidates\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B RSFT candidate generation (N=8, T=0.7). Scale ablation: smallest model RSFT candidates for CED scoring. plan_006 claim=3.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_002_test_eval_s44_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"DocRED test set evaluation for RSFT-CED s44 (best dev config). Final benchmark numbers for paper submission; test set performance confirms dev set gains are not overfitting artifacts.\\\"}, \\\"plan_006_qwen3_8b_no_evidence_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-8B no-evidence SFT baseline for evidence tax measurement at 8B scale. If 8B no-evi rel_f1 ≈ 8B evidence-SFT rel_f1, confirms that 8B absorbs evidence cost (tax≈0).\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B no-evidence SFT baseline for evidence tax measurement at 1.7B scale. Paired with evidence-SFT to quantify whether evidence generation constrains or helps small model RE performance.\\\"}, \\\"plan_006_qwen3_1_7b_sft_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: smallest model expected to show highest evidence tax due to capacity-constrained multi-task optimization.\\\"}, \\\"plan_006_qwen3_8b_sft_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-8B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: larger model should achieve higher rel_f1 than 4B (0.4057) and 1.7B baselines, with lower evidence tax due to greater capacity.\\\"}, \\\"reeval_sft_baseline_d076\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Re-eval Qwen3-4B SFT baseline under D076 unified protocol (batch_size=4, no-quantize, max_new_tokens=1024, seed=42). Required as canonical comparison point for all RSFT/GRPO experiments and evidence tax computation.\\\"}, \\\"plan_006_qwen3_1_7b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B evidence-SFT eval under D076 protocol. Establishes smallest-scale SFT baseline; evidence tax at 1.7B predicted negative (evidence helps small models by constraining over-prediction).\\\"}, \\\"plan_006_qwen3_8b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-8B evidence-SFT eval under D076 unified protocol. Establishes 8B-scale SFT baseline for evidence tax measurement (paired with no-evidence eval) and RSFT improvement quantification.\\\"}, \\\"plan_016_llama_3_1_8b_no_evidence_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B no-evidence SFT baseline for cross-family evidence tax measurement. Paired with evidence-SFT to quantify evidence generation cost on a non-Qwen architecture at 8B scale.\\\"}, \\\"plan_016_llama_3_1_8b_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B can be SFT-trained for evidence-grounded DocRE with the same pipeline as Qwen3 family, enabling cross-family generalization claims for the FREIGE framework.\\\"}, \\\"plan_007_redocred_4b_sft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"FREIGE SFT model trained on DocRED transfers to Re-DocRED without re-training: if Ign-F1 drop <5pp and Evi-F1 maintains, the learned evidence grounding generalizes across annotation schemes.\\\"}, \\\"plan_006_qwen3_8b_no_evidence_eval_v2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"8B model capacity absorbs evidence generation cost: no-evidence SFT and evidence-SFT should produce near-identical rel_f1, demonstrating evidence tax≈0 at 8B scale (contrasting with 4B where tax=-7.5pp).\\\"}, \\\"plan_016_llama_3_1_8b_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B no-evidence SFT should achieve similar rel_f1 to evidence-SFT (tax≈0), cross-family validating the 8B-scale evidence absorption pattern observed in Qwen3-8B.\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval_v3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"1.7B model capacity is insufficient to jointly optimize RE and evidence generation: no-evidence SFT should outperform evidence-SFT on rel_f1, revealing positive evidence tax at small scale (opposite to 8B where tax≈0).\\\"}, \\\"plan_016_llama_3_1_8b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B SFT with evidence generation should achieve comparable rel_f1 to Qwen3-8B SFT, establishing cross-family baseline for evidence tax measurement. Evidence tax at 8B scale predicted near-zero based on Qwen3-8B pattern.\\\"}, \\\"plan_016_llama_grpo_qlora\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"QLoRA GRPO catastrophic decoupling (format gaming + zero IE ability) is not Qwen-specific: LLaMA-3.1-8B under identical QLoRA GRPO training should exhibit the same failure mode (grad_norm→0, loss→0, rel_f1→0). Cross-family validation of C2.\\\"}, \\\"plan_006_qwen3_8b_rsft_candidates\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Qwen3-8B RSFT candidate generation (N=8, T=0.7). Generates rejection sampling candidates for subsequent CED scoring and filtering. plan_006 claim=3.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_candidates_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT candidate gen r3 (N=8, T=0.7, start_idx=64 resume). Exclusive cuda:2 after GRPO kill.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_007_redocred_rsft_eval_r5\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED-RSFT gains transfer to Re-DocRED (r5, correct 3-param loading: base→SFT→RSFT)\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_007_redocred_rsft_eval_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED-RSFT gains transfer to Re-DocRED (r4, correct 3-param loading: base→SFT→RSFT)\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_002_test_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_007_redocred_rsft_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-DocRED RSFT eval r3 (config fix: model_path=base, sft_adapter=RSFT ckpt). Verify CED-RSFT gains transfer cross-dataset.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_007_redocred_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_014_no_evidence_eval_d076\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B no-evidence SFT eval under D076 unified protocol (batch_size=4, max_new_tokens=1024, seed=42, no-quantize). Required for clean scaling comparison across 1.7B/4B/8B.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_016_llama_rsft_candidates_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_candidates\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\\\"}, \\\"plan_007_redocred_4b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval_v2r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval_v2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_8b_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"reeval_flat_nli_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval flat-NLI RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 eval_plan_001_flat_nli 用了 batch_size=16。Paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"reeval_ced_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval CED RSFT s44 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + seed=44. 原 eval 用了 batch_size≈16 且 seed=42（错误）。Paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"reeval_ced_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 mvp2_eval_rsft_r2b_maxtok1536_r2 用了 batch_size=8 + max_new_tokens=1536。Paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"reeval_flat_nli_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_006_qwen3_1_7b_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"reeval_flat_nli_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval flat-NLI RSFT s43 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + --max_new_tokens 1024. 原 reeval_flat_nli_s43 用了 batch_size=16 导致协议不一致。C3 paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_rsft_ced_s45\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_rsft_ced_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of CED RSFT seed=43 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 4 个 seed。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_014_no_evidence_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Retry of eval_plan_014_no_evidence with corrected command: --model_path 传底座 Qwen3-4B, --sft_adapter 传 SFT no-evidence adapter。修复 adapter 检测逻辑冲突。plan_id=plan_014, claim=1。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_ced_reranker_poc\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_flat_nli_seed45\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_flat_nli_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"rsft_ced_s45_train_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED RSFT seed=45 训练（r4 重试，r3 因 cuda:2 orphan PID 276148 OOM 失败）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44，s43 在 cuda:1 训练中）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"rsft_ced_s43_train_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_014_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Dev set eval of SFT-no-evidence model (plan_014). 核心目标：对比标准 SFT rel_f1=0.4057 vs 不输出 evidence 的 SFT rel_f1（隔离 evidence generation 代价）。只评估 rel_f1，不评估 evi_f1（输出无 evidence）。plan_id=plan_014, claim=1。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_ced_s45_train_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_ced_s45_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"rsft_ced_s43_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED RSFT seed=43 训练（r2 重试，修正 cwd 错误）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"reeval_rsft_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval RSFT top_k=3 WITH --sft_adapter (D064 bug fix). 原 eval_plan_008_rsft_topk3 因缺 --sft_adapter 被 killed。对比 CED RSFT top_k=1 (rel_f1≈0.46) 和 SFT baseline (0.4057)。\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"rsft_ced_s43_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_ced_s45_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"reeval_flat_nli_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval flat-NLI RSFT seed=43 WITH --sft_adapter (D064 bug fix). 原 eval_plan_001_flat_nli_s43 因缺 --sft_adapter 导致 rel_f1=0.0022 无效。对比 flat-NLI s42 (rel_f1=0.4539) 和 CED RSFT mean (0.4596)。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_003_edcr_diagnostic\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"EDCR cross-method diagnostic table: 计算所有 evidence-producing 方法（SFT baseline, RSFT-CED best, RSFT-flatNLI best, CED-reranker）的 EDCR，验证 EDCR 作为独立评估指标的诊断能力。plan_id=plan_003, claim=4。GPU 预算 2h。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_flat_nli_seed44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_012_dpo_1ep_fixed_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_001_flat_nli_seed44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_009_dynamics_figure\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO forgetting dynamics 3-panel figure: QLoRA vs BF16 GRPO 的 rel_f1/evi_f1/EDCR 训练轨迹对比。支撑 Claim 3 (task decoupling 是 QLoRA-specific)。plan_id=plan_009。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_001_flat_nli_seed45\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_011_bf16_g8_step_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_011_eval_g8_bf16_ckpt100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT seed=44 checkpoint. First MVP-2 judgement data point. Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798 (SFT baseline).\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_008_topk3_fixed\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_012_dpo_1ep_fixed\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_008_rsft_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\", \\\"hypothesis\\\": \\\"RSFT top_k=3 dev eval: 对比 top_k=1 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1≈0.4057)。验证更多候选是否提升证据质量。\\\"}, \\\"plan_012_dpo_ced\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_012_dpo_ced_1ep\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"DPO+CED 1 epoch retraining: plan_012_dpo_ced 3 epochs 严重过拟合 (rewards_accuracy=1.0, margins 9x膨胀, entropy崩塌)。重训 1 epoch 验证 early stopping 是否消除 overfitting confound。对比 plan_012 3ep + RSFT (rel_f1=0.46) + SFT baseline (rel_f1=0.4057)。\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"eval_plan_001_flat_nli_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"eval_plan_012_dpo_ced_1ep\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_008_rsft_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT top_k=3 训练：用 CED-filtered 的 top-3 候选进行 rejection sampling fine-tuning，验证更多候选是否比 top_k=1 (rel_f1≈0.46) 带来更好的证据质量。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_001_flat_nli_seed43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_009_flatnli_reward_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_009_extract_reward_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"eval_sft_baseline_noquant\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_009_flatnli_reward_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"eval_plan_012_dpo_ced_ckpt400\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_009_forgetting_figure\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_014_sft_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_014_sft_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT-without-evidence ablation: 训练只输出 relation triples（不含 evidence sentences）的 SFT 模型。量化 joint evidence generation 对 extraction 的代价（当前 rel_f1=0.4057 vs 只抽关系的 LMRC 60.7 的 gap 有多少来自 evidence 负担）。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_002_test_eval_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_001_rsft_flat_nli\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"flat-NLI RSFT ablation: 用 flat-NLI scoring（p_pos 概率，无 contrastive margin）筛选的 2691 样本做 RSFT。对比 CED scoring RSFT（2718 样本）。验证 CED 的对比性 margin 是否是关键因素。如 flat-NLI RSFT ≈ CED RSFT → CED 无增益；如 CED RSFT 显著优于 → contrastive margin 关键。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_001_flat_nli\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Dev eval of flat-NLI RSFT (plan_001). 对比 CED RSFT (3-seed mean rel_f1=0.4596). flat-NLI ≈ CED → CED contrastive margin 无增益; CED >> flat-NLI → margin 关键。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_grpo_g8_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval GRPO G=8 bf16 checkpoints 80/90/100 on full dev set (985 docs). 验证 catastrophic forgetting 是否在 bf16 LoRA 下复现。rel_f1>0.30 → forgetting 不复现 (QLoRA-specific); rel_f1<0.05 → 复现 (C2 加强)。对比: SFT rel_f1=0.4057, QLoRA GRPO rel_f1=0.2167 (catastrophic).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_015_grpo_g4_bf16_v3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P2 robustness check: bf16 LoRA GRPO G=4, kl=0.01, lr=5e-6。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean single-variable quantization ablation (Δ=+23.8pp)。v3 仅为 robustness data point，lr=5e-6 与对照组 lr=5e-5 不一致。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_015_grpo_g4_bf16_v2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Robustness check: bf16 LoRA GRPO 在 G=4, kl=0, lr=5e-6 条件下是否也防止 catastrophic forgetting。非 single-variable ablation（kl/lr/G 均与 QLoRA 对照组不同）。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean quantization ablation。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_015_grpo_g4_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"bf16 LoRA GRPO clean control: 与原始 QLoRA GRPO 仅改 quantization（4-bit → bf16），保持 G=4, kl=0, CED reward 不变。验证 catastrophic forgetting 是否由 QLoRA quantization 导致。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_011_grpo_g8_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO G=8 bf16 LoRA: 验证 catastrophic forgetting 是否在 bf16（非 QLoRA 4-bit）下仍复现。CED reward + kl_coef=0.01, 100 steps。如仍 fail → 加强 Claim 3\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_011_grpo_g8_bf16_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_004_dreeam_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Phase A: 复现 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1≈54.15, RE-F1≈63.49。论文报告的57.34是student model在test set的结果，需4阶段self-training pipeline。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2b_maxtok1536_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). Retry with correct model stack (Base+SFT+RSFT). If EDCR improves significantly (from 0.6609 toward 0.71+), truncation is the cause. If unchanged, distractor citation is genuine RSFT behavior.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_001_flat_nli_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"flat-NLI scoring 前置步骤：用 flat_nli 模式（p_pos 概率，无 contrastive margin）对 RSFT 生成候选打分并筛选训练数据。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798. Retry of mvp2_eval_rsft_s43 (fixed arg names).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_ced_scoring_topk3_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Retry with HF_HUB_OFFLINE=1 (NLI model cached locally).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_train_r1_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT training seed=44 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2b\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of r2b (1 epoch, alpha=32, lr=1e-5, clean data). Ablation: conservative LoRA scaling vs r2a/r1. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2a\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of r2a (1 epoch, alpha=128, clean data). Ablation: 1 epoch vs 3 epoch (r1). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT r1 (seed=42). Same pipeline as s44 eval (985 docs, no-quantize). Need 3-seed data for complete_mvp. s44 PASS: rel_f1=0.4655, evi_f1=0.8087.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_sft_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT baseline eval using identical eval protocol as GRPO evals (eval_lr5e6_ckpt20.sh). Required for MVP-2 core comparison: CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp. Prior SFT eval (r3) used different eval path; this ensures apple-to-apple comparison.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2b_maxtok1536\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). If EDCR improves significantly (from 0.6609 toward 0.71+), current EDCR gap is truncation artifact, not model issue. If EDCR unchanged, distractor citation is genuine RSFT behavior.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_ced_scoring_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Answers: does CED filtering strictness affect RSFT training quality?\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_r2b\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT r2b: data fix + training dynamics fix (1 epoch + filter truncated + LoRA alpha=32/r=64 scaling 0.5 + lr=1e-5). Isolates: is conservative LoRA scaling the key factor? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_r2a\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT r2a: data fix only (1 epoch + filter 170 truncated JSON → 2548 samples). Same LoRA alpha=128/r=64, lr=2e-5 as r1. Isolates: does 1 epoch + clean data alone fix the ontology collapse? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_diagnosis\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT failure root cause: rel_f1=0.0483 vs SFT 0.4057. Diagnose: training data distribution (relation count), step-170 checkpoint output analysis, SFT vs RSFT data comparison.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_ced_kl001_r4_last\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_kl001_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr + bash -c wrapping)\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_kl001_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr → --learning_rate)\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_train_r2_fix\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT r2 fix: 4 fixes based on r1 diagnosis. 1) 1 epoch (vs 3), 2) LoRA alpha=32/r=64 (scaling 0.5 vs 2.0), 3) filtered truncated JSON (~2548 vs 2718 samples), 4) lr=1e-5 (vs 2e-5). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_train_r1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT training seed=43 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_rsft_train_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT training on CED-filtered data (2718 samples, mean CED=0.668). SFT warmup baseline: rel_f1=0.4057, evi_f1=0.798. Pass criteria: rel_f1 > 0.4057 AND evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring + filtering on 4 shard RSFT generations. top_k=1, f1_threshold=0.1. 21952 → 2718 selected (12.4%).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 0/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 3/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 2/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 1/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation phase: SFT model generates N=8 candidate outputs per training sample at T=0.7. CED scoring + filtering后作为 RSFT 训练数据。D031 pivot 方向。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_diversity_probe\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT viability check: SFT model output diversity at T=0.7/1.0 with N=8 generations. Pass criteria: unique triple-sets >= 5/8.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-100 eval: lr=5e-6 GRPO at step 100 (halfway point). Checkpoint-100 已保存。与 kl001_r4 的 step-100 (rel_f1=0.217) 形成直接对比。Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_ced_lr5e6_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D030/P0: lr=5e-6 (10x lower than ced_kl001_r4) prevents catastrophic forgetting while maintaining CED reward improvement. Community consensus GRPO+QLoRA lr=5e-6~1e-5. Pass criteria: ckpt-20 rel_f1 > 0.30. Extra monitoring: pred_count + recall trend.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt80\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-80 eval: lr=5e-6 GRPO at step 80. 训练轨迹继续——ckpt-20 FAIL (0.0077), ckpt-40/60 待出. Step 80 reward=0.283 (回升), format_reward=0.249. Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt60_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-60 eval retry: 原 submit_on_allocated 失败 (pid=unknown). 手动 SSH 启动 /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh. Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt60\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-60 eval: lr=5e-6 GRPO at step 60. 训练轨迹数据点——ckpt-20 catastrophic forgetting (rel_f1=0.0077)，需看后续 checkpoint 是否恢复。Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt40_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-tracking orphan PID 101842 for P0 ckpt-40 eval (lr=5e-6 GRPO step 40). Original exp auto-failed due to cron/PID mismatch. Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt20\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-20 early eval: lr=5e-6 GRPO at step 20. Pass criteria: rel_f1 > 0.30 (no catastrophic forgetting). Key MVP gate for P0.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_rp_r2_ckpt20\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0+P1 ckpt-20 eval: lr=5e-6 + recall_penalty GRPO at step 20. Director killed rp_r2 training (loss divergence), but ckpt-20 eval needed to close P0+P1 comparison line. Pass criteria: rel_f1 > 0.30 AND pred_count >= 9720.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt40\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-40 eval: lr=5e-6 GRPO at step 40 (where f1_reward first rises to 0.038). Director 新判定框架: ckpt-20 FAIL + ckpt-40 PASS → P0 判 PASS。Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_lr5e6_rp_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D032/P0+P1 retry: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 (lr5e6_r1) isolates CED shortcut fix contribution. Retry of rp_r1 which failed due to bash quoting.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_ced_kl001_r4_multi\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_lr5e6_rp_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D032/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_lr5e6_p1_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D031/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 15000 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_ced_kl001_r4_step90\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval true best checkpoint (step 90, reward=1.370). Critical after ckpt-50 showed reward hacking (rel_f1 -24.9pp). If step 90 also fails, CED reward design has fundamental issue.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_ced_kl001_r4_ckpt7080\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-run failed ckpt-70/80 eval from crashed high eval (cuda:3 OOM). Completes 10-checkpoint trajectory for paper negative result analysis.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_eval_ced_kl001_r4_high\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"High-end checkpoint eval (60,70,80,90) on cuda:3, complementing cuda:2 low-end eval. Step 90 is true best checkpoint (reward=1.370). D024 directive.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_eval_ced_kl001_r4_step100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval ced_kl001_r4 last checkpoint (step 100) to compare with best-reward checkpoint (step 50). If best ≠ last, the gap measures training stability under batch_size=1 GRPO variance.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_ced_kl001_r4_ckpt90\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval ced_kl001_r4 best-reward checkpoint (step 90, reward=1.370, f1=0.720) — this is the primary MVP-2 judgment checkpoint. If evi_f1 ≥ SFT baseline (0.7979) + 2pp = 0.8179, MVP-2 passes.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_ced_kl001_r4_ckpt10\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_ced_kl001_r4_early\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_flatnli_r6\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Flat-NLI reward with kl_coef=0.01 + num_generations=8 from SFT scratch (not resume). 100-step probe to verify stability. Same D020 config as ced_kl001_r4 (which is healthy). Tests whether flat-NLI reward type works under stable training config.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_ced_kl001_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_grpo_extract_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0.01 + num_generations=8 trains stably. 100-step probe parallel ablation with ced_kl001_r4 (CED reward) to compare reward type impact under identical stability config.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_flatnli_r5\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Flat-NLI reward with kl_coef=0.01 + num_generations=8 prevents mode collapse. Resume from flatnli_r3 checkpoint-100 (healthy). 100-step probe (steps 100→200) to verify stability before full run.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_sft_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_grpo_extract_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_flatnli_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_kl001\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_r5\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_flatnli_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_sft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_flatnli_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_extract_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_extract\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Extraction-only reward (format+F1, no CED) establishes GRPO baseline — CED r3 should exceed this on Evi-F1\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_flatnli\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Flat-NLI reward (non-contrastive) improves Evi-F1 over extraction-only but less than CED — validates contrastive component's incremental value\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + stable training (num_iterations=1, KL early stop at 100) + kl_coef=0.05 improves Evi-F1 over SFT baseline\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"precompute_nli_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_sft_warmup\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"smoke_test_grpo\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp1_ced_signal\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}}, \\\"count\\\": 237, \\\"total\\\": 237, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.7213}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_s44_r2\": {\"status\": \"RUNNING\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\"}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"RUNNING\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"success\"}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"failed\"}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"failed\"}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_train\": {\"status\": \"RUNNING\", \"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\"}, \"plan017_14b_sft\": {\"status\": \"RUNNING\"}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard3\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard1\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard2\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard0\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"conclusion\": \"killed\"}, \"plan019_8b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\", \"conclusion\": \"success\"}, \"plan019_8b_sft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\", \"conclusion\": \"success\"}, \"grpo_bf16_g4_ckpt200_eval\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\", \"conclusion\": \"success\"}, \"random_rsft_k1_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s44_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s43_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"conclusion\": \"success\"}, \"plan019_8b_sft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\", \"conclusion\": \"success\"}, \"wave1_grpo_bf16_g4\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\", \"conclusion\": \"success\"}, \"random_rsft_k1_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\", \"conclusion\": \"success\"}, \"grpo_bf16_g4_ckpt100_eval\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"conclusion\": \"failed\"}, \"wave1_sft_4b_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"conclusion\": \"failed\"}, \"wave1_sft_4b_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"SFT 4B seed43 eval (D076 protocol): baseline SFT performance for seed43. Paired with s44 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"conclusion\": \"failed\"}, \"seed_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s44\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline for Qwen3-4B seed44: second seed for SFT baseline. Paired with seed43 for mean±std reporting. Expected rel_f1 similar to seed43 (~50.5±1pp).\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s43\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline for Qwen3-4B seed43: standard SFT without CED filtering. Paired with RSFT to measure CED filtering gain. Expected rel_f1 ~50.5 based on prior 8B SFT results scaled down.\", \"conclusion\": \"success\"}, \"d102_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\", \"conclusion\": \"killed\"}, \"seed_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_llama_k1_s43_train\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。\", \"conclusion\": \"success\"}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"conclusion\": \"success\"}, \"d102_8b_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3018 samples vs 9041），预期 rel_f1 与 k=3 相当或略有变化，验证 k=1 在 8B 上同样有效。\", \"conclusion\": \"success\"}, \"d102_llama_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。\", \"conclusion\": \"success\"}, \"d102_1_7b_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：1.7B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3021 samples vs 9042），在最小模型上验证 k=1 RSFT 效果。\", \"conclusion\": \"success\"}, \"seed_comparison_prep\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan006_1_7b_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_s43_dev_eval_preds\": {\"status\": \"DONE\", \"hypothesis\": \"Eval RSFT-s43 (CED-scored) on DocRED dev with predictions saved. Prerequisite for Lead 1 CED evidence filtering: per-sentence NLI scoring requires full prediction outputs.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT model (checkpoint-1698) on DocRED dev. Retry after disk-full crash. Validates CED-filtered RSFT at smallest model scale in scaling study.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_r3_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data (9041 samples) on Qwen3-8B, resume from checkpoint-750 after disk-full crash. At 8B scale, CED-filtered RSFT should achieve highest absolute performance in scaling study.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_seed43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5219. If seed 43 gives similar result (±1pp, i.e., 0.51-0.53), the 1.7B scaling study datapoint is robust.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate 1.7B RSFT test set predictions for CodaLab submission. 1.7B RSFT dev rel_f1=0.5219, expect similar performance on test.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate 8B RSFT test set predictions for CodaLab submission. 8B RSFT dev rel_f1=0.5606, expect similar performance on test.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust against seed variance.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43\": {\"status\": \"DONE\", \"hypothesis\": \"Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed variance.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.\", \"conclusion\": \"failed\"}, \"lead2_ckpt20_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate GRPO checkpoint-20 from RSFT base (lead2_rsft_grpo_ced_r2) on DocRED dev. If RSFT→GRPO preserves/improves rel_f1 over RSFT baseline (0.4601), it validates the RSFT→GRPO training pipeline as viable.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate Qwen3-8B RSFT (CED-scored data, 9041 samples) on DocRED dev. At 8B scale with near-zero evidence tax, CED-RSFT should achieve highest absolute Ign-F1 in the scaling study.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_seed43\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with seed 43 on Qwen3-1.7B will produce comparable performance to other seeds, validating seed robustness for the scaling study\", \"conclusion\": \"success\"}, \"post_hoc_bm25_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Post-hoc BM25 evidence retrieval on SFT-no-evidence predictions: if retrieving evidence after RE produces comparable joint Evi-F1 and EDCR to jointly trained RSFT, then joint generation is unnecessary. Expect RSFT to have better evidence quality (lower EDCR) due to training-time evidence grounding.\", \"conclusion\": \"success\"}, \"lead1_ced_evidence_filter\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"hypothesis\": \"Post-hoc CED-based evidence filtering on RSFT predictions: removing low-NLI-score evidence sentences at inference time should improve Evi-F1 and EDCR by eliminating distractor citations, without affecting rel_f1.\"}, \"plan_006_qwen3_8b_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data (9041 samples) on Qwen3-8B will improve rel_f1 over SFT baseline. At 8B scale with near-zero evidence tax, CED-filtered RSFT should achieve the highest absolute performance in the model scaling study.\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_rsft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT model on DocRED dev to measure rel_f1 improvement over SFT baseline. Validates that CED-filtered RSFT generalizes to smallest model scale (1.7B) in the scaling study.\", \"conclusion\": \"failed\"}, \"rsft_s44_dev_eval_preds\": {\"status\": \"DONE\", \"hypothesis\": \"Re-run RSFT s44 dev eval with predictions saved, as prerequisite for CED evidence filtering experiment (线索1: inference-time distractor citation removal). Predictions needed for per-sentence NLI scoring.\", \"conclusion\": \"failed\"}, \"lead2_rsft_grpo_ced_r2\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT→bf16 GRPO two-stage (retry with --data_dir fix): starting from merged RSFT-s43 checkpoint (rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should improve evidence quality (EDCR) while preserving rel_f1.\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_train_r3\": {\"status\": \"DONE\", \"hypothesis\": \"bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues seen in r1/r2 attempts\", \"conclusion\": \"success\"}, \"lead2_rsft_grpo_ced\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT→bf16 GRPO two-stage: starting from RSFT best checkpoint (s43, rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should further improve evidence quality (EDCR) while preserving rel_f1, because RSFT provides stable base preventing catastrophic forgetting seen in SFT→GRPO.\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_8b_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring on Qwen3-8B RSFT candidates (24216 gens from 3027 docs) will produce high-quality filtered training data. At 8B scale with near-zero evidence tax, CED-filtered RSFT should yield further gains over an already strong SFT baseline.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data on Qwen3-1.7B will improve relation extraction F1 over SFT baseline by selectively reinforcing high-quality extraction patterns, similar to gains seen on 4B model\", \"conclusion\": \"success\"}, \"plan_002_test_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT-CED s44 (best dev config, rel_f1=0.4655) maintains improvement over SFT on held-out test set, confirming CED-filtered rejection sampling gains are not dev-set overfitting. Test Ign-F1 should exceed SFT test baseline.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_candidates_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Resuming 8B candidate generation from idx 2701 will complete the full RSFT candidate set needed for reward-based filtering and RSFT training\", \"conclusion\": \"success\"}, \"plan_016_llama_rsft_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families (Qwen→LLaMA).\", \"conclusion\": \"failed\"}, \"plan_016_llama_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring (NLI contrastive discrimination) can effectively filter 1.7B model candidates despite lower generation quality: NLI-based selection should identify high-quality evidence samples even from a capacity-limited generator.\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"hypothesis\": \"CED-RSFT improvements on DocRED should transfer to Re-DocRED: RSFT model should outperform SFT baseline on Re-DocRED Ign-F1, demonstrating cross-dataset generalization of rejection sampling gains.\"}, \"plan_006_qwen3_1_7b_rsft_candidates\": {\"status\": \"DONE\", \"hypothesis\": \"Qwen3-1.7B RSFT candidate generation (N=8, T=0.7). Scale ablation: smallest model RSFT candidates for CED scoring. plan_006 claim=3.\", \"conclusion\": \"success\"}, \"plan_002_test_eval_s44_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"DocRED test set evaluation for RSFT-CED s44 (best dev config). Final benchmark numbers for paper submission; test set performance confirms dev set gains are not overfitting artifacts.\"}, \"plan_006_qwen3_8b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-8B no-evidence SFT baseline for evidence tax measurement at 8B scale. If 8B no-evi rel_f1 ≈ 8B evidence-SFT rel_f1, confirms that 8B absorbs evidence cost (tax≈0).\"}, \"plan_006_qwen3_1_7b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-1.7B no-evidence SFT baseline for evidence tax measurement at 1.7B scale. Paired with evidence-SFT to quantify whether evidence generation constrains or helps small model RE performance.\"}, \"plan_006_qwen3_1_7b_sft_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-1.7B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: smallest model expected to show highest evidence tax due to capacity-constrained multi-task optimization.\"}, \"plan_006_qwen3_8b_sft_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-8B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: larger model should achieve higher rel_f1 than 4B (0.4057) and 1.7B baselines, with lower evidence tax due to greater capacity.\"}, \"reeval_sft_baseline_d076\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Re-eval Qwen3-4B SFT baseline under D076 unified protocol (batch_size=4, no-quantize, max_new_tokens=1024, seed=42). Required as canonical comparison point for all RSFT/GRPO experiments and evidence tax computation.\"}, \"plan_006_qwen3_1_7b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-1.7B evidence-SFT eval under D076 protocol. Establishes smallest-scale SFT baseline; evidence tax at 1.7B predicted negative (evidence helps small models by constraining over-prediction).\"}, \"plan_006_qwen3_8b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-8B evidence-SFT eval under D076 unified protocol. Establishes 8B-scale SFT baseline for evidence tax measurement (paired with no-evidence eval) and RSFT improvement quantification.\"}, \"plan_016_llama_3_1_8b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B no-evidence SFT baseline for cross-family evidence tax measurement. Paired with evidence-SFT to quantify evidence generation cost on a non-Qwen architecture at 8B scale.\"}, \"plan_016_llama_3_1_8b_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B can be SFT-trained for evidence-grounded DocRE with the same pipeline as Qwen3 family, enabling cross-family generalization claims for the FREIGE framework.\"}, \"plan_007_redocred_4b_sft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"FREIGE SFT model trained on DocRED transfers to Re-DocRED without re-training: if Ign-F1 drop <5pp and Evi-F1 maintains, the learned evidence grounding generalizes across annotation schemes.\"}, \"plan_006_qwen3_8b_no_evidence_eval_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"8B model capacity absorbs evidence generation cost: no-evidence SFT and evidence-SFT should produce near-identical rel_f1, demonstrating evidence tax≈0 at 8B scale (contrasting with 4B where tax=-7.5pp).\"}, \"plan_016_llama_3_1_8b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B no-evidence SFT should achieve similar rel_f1 to evidence-SFT (tax≈0), cross-family validating the 8B-scale evidence absorption pattern observed in Qwen3-8B.\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"1.7B model capacity is insufficient to jointly optimize RE and evidence generation: no-evidence SFT should outperform evidence-SFT on rel_f1, revealing positive evidence tax at small scale (opposite to 8B where tax≈0).\"}, \"plan_016_llama_3_1_8b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B SFT with evidence generation should achieve comparable rel_f1 to Qwen3-8B SFT, establishing cross-family baseline for evidence tax measurement. Evidence tax at 8B scale predicted near-zero based on Qwen3-8B pattern.\"}, \"plan_016_llama_grpo_qlora\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"QLoRA GRPO catastrophic decoupling (format gaming + zero IE ability) is not Qwen-specific: LLaMA-3.1-8B under identical QLoRA GRPO training should exhibit the same failure mode (grad_norm→0, loss→0, rel_f1→0). Cross-family validation of C2.\"}, \"plan_006_qwen3_8b_rsft_candidates\": {\"status\": \"DONE\", \"hypothesis\": \"Qwen3-8B RSFT candidate generation (N=8, T=0.7). Generates rejection sampling candidates for subsequent CED scoring and filtering. plan_006 claim=3.\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_candidates_r3\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT candidate gen r3 (N=8, T=0.7, start_idx=64 resume). Exclusive cuda:2 after GRPO kill.\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r5\": {\"status\": \"DONE\", \"hypothesis\": \"CED-RSFT gains transfer to Re-DocRED (r5, correct 3-param loading: base→SFT→RSFT)\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r4\": {\"status\": \"DONE\", \"hypothesis\": \"CED-RSFT gains transfer to Re-DocRED (r4, correct 3-param loading: base→SFT→RSFT)\", \"conclusion\": \"failed\"}, \"plan_002_test_rsft_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_007_redocred_rsft_eval_r3\": {\"status\": \"DONE\", \"hypothesis\": \"Re-DocRED RSFT eval r3 (config fix: model_path=base, sft_adapter=RSFT ckpt). Verify CED-RSFT gains transfer cross-dataset.\", \"conclusion\": \"failed\"}, \"plan_007_redocred_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_014_no_evidence_eval_d076\": {\"status\": \"DONE\", \"hypothesis\": \"4B no-evidence SFT eval under D076 unified protocol (batch_size=4, max_new_tokens=1024, seed=42, no-quantize). Required for clean scaling comparison across 1.7B/4B/8B.\", \"conclusion\": \"success\"}, \"plan_016_llama_rsft_candidates_r2\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_candidates\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"hypothesis\": \"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\"}, \"plan_007_redocred_4b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v2r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_8b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s42\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval flat-NLI RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 eval_plan_001_flat_nli 用了 batch_size=16。Paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"reeval_ced_s44\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval CED RSFT s44 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + seed=44. 原 eval 用了 batch_size≈16 且 seed=42（错误）。Paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"reeval_ced_s42\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 mvp2_eval_rsft_r2b_maxtok1536_r2 用了 batch_size=8 + max_new_tokens=1536。Paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"reeval_flat_nli_s44\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan_006_qwen3_1_7b_sft\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval flat-NLI RSFT s43 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + --max_new_tokens 1024. 原 reeval_flat_nli_s43 用了 batch_size=16 导致协议不一致。C3 paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"eval_rsft_ced_s45\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"success\"}, \"eval_rsft_ced_s43\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of CED RSFT seed=43 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 4 个 seed。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"success\"}, \"eval_plan_014_no_evidence_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Retry of eval_plan_014_no_evidence with corrected command: --model_path 传底座 Qwen3-4B, --sft_adapter 传 SFT no-evidence adapter。修复 adapter 检测逻辑冲突。plan_id=plan_014, claim=1。\", \"conclusion\": \"success\"}, \"mvp2_ced_reranker_poc\": {\"status\": \"DONE\", \"hypothesis\": \"CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.\", \"conclusion\": \"success\"}, \"eval_flat_nli_seed45\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。\", \"conclusion\": \"success\"}, \"eval_flat_nli_s44\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。\", \"conclusion\": \"success\"}, \"rsft_ced_s45_train_r4\": {\"status\": \"DONE\", \"hypothesis\": \"CED RSFT seed=45 训练（r4 重试，r3 因 cuda:2 orphan PID 276148 OOM 失败）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44，s43 在 cuda:1 训练中）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"success\"}, \"rsft_ced_s43_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_plan_014_no_evidence\": {\"status\": \"DONE\", \"hypothesis\": \"Dev set eval of SFT-no-evidence model (plan_014). 核心目标：对比标准 SFT rel_f1=0.4057 vs 不输出 evidence 的 SFT rel_f1（隔离 evidence generation 代价）。只评估 rel_f1，不评估 evi_f1（输出无 evidence）。plan_id=plan_014, claim=1。\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_ced_s43_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"CED RSFT seed=43 训练（r2 重试，修正 cwd 错误）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"failed\"}, \"reeval_rsft_topk3\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval RSFT top_k=3 WITH --sft_adapter (D064 bug fix). 原 eval_plan_008_rsft_topk3 因缺 --sft_adapter 被 killed。对比 CED RSFT top_k=1 (rel_f1≈0.46) 和 SFT baseline (0.4057)。\", \"conclusion\": \"negative\"}, \"rsft_ced_s43_train\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s43\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval flat-NLI RSFT seed=43 WITH --sft_adapter (D064 bug fix). 原 eval_plan_001_flat_nli_s43 因缺 --sft_adapter 导致 rel_f1=0.0022 无效。对比 flat-NLI s42 (rel_f1=0.4539) 和 CED RSFT mean (0.4596)。\", \"conclusion\": \"success\"}, \"plan_003_edcr_diagnostic\": {\"status\": \"DONE\", \"hypothesis\": \"EDCR cross-method diagnostic table: 计算所有 evidence-producing 方法（SFT baseline, RSFT-CED best, RSFT-flatNLI best, CED-reranker）的 EDCR，验证 EDCR 作为独立评估指标的诊断能力。plan_id=plan_003, claim=4。GPU 预算 2h。\", \"conclusion\": \"success\"}, \"eval_flat_nli_seed44\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.\", \"conclusion\": \"killed\"}, \"eval_plan_012_dpo_1ep_fixed_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"plan_001_flat_nli_seed44\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_009_dynamics_figure\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO forgetting dynamics 3-panel figure: QLoRA vs BF16 GRPO 的 rel_f1/evi_f1/EDCR 训练轨迹对比。支撑 Claim 3 (task decoupling 是 QLoRA-specific)。plan_id=plan_009。\", \"conclusion\": \"success\"}, \"plan_001_flat_nli_seed45\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_011_bf16_g8_step_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_011_eval_g8_bf16_ckpt100\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT seed=44 checkpoint. First MVP-2 judgement data point. Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798 (SFT baseline).\", \"conclusion\": \"killed\"}, \"eval_plan_008_topk3_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_012_dpo_1ep_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_008_rsft_topk3\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"hypothesis\": \"RSFT top_k=3 dev eval: 对比 top_k=1 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1≈0.4057)。验证更多候选是否提升证据质量。\"}, \"plan_012_dpo_ced\": {\"status\": \"DONE\", \"hypothesis\": \"DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。\", \"conclusion\": \"negative\"}, \"plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"hypothesis\": \"DPO+CED 1 epoch retraining: plan_012_dpo_ced 3 epochs 严重过拟合 (rewards_accuracy=1.0, margins 9x膨胀, entropy崩塌)。重训 1 epoch 验证 early stopping 是否消除 overfitting confound。对比 plan_012 3ep + RSFT (rel_f1=0.46) + SFT baseline (rel_f1=0.4057)。\", \"conclusion\": \"negative\"}, \"eval_plan_001_flat_nli_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"plan_008_rsft_topk3\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT top_k=3 训练：用 CED-filtered 的 top-3 候选进行 rejection sampling fine-tuning，验证更多候选是否比 top_k=1 (rel_f1≈0.46) 带来更好的证据质量。\", \"conclusion\": \"success\"}, \"plan_001_flat_nli_seed43\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_009_flatnli_reward_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_009_extract_reward_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_sft_baseline_noquant\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_009_flatnli_reward_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_plan_012_dpo_ced_ckpt400\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_009_forgetting_figure\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"hypothesis\": \"SFT-without-evidence ablation: 训练只输出 relation triples（不含 evidence sentences）的 SFT 模型。量化 joint evidence generation 对 extraction 的代价（当前 rel_f1=0.4057 vs 只抽关系的 LMRC 60.7 的 gap 有多少来自 evidence 负担）。\", \"conclusion\": \"success\"}, \"plan_002_test_eval_s44\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_001_rsft_flat_nli\": {\"status\": \"DONE\", \"hypothesis\": \"flat-NLI RSFT ablation: 用 flat-NLI scoring（p_pos 概率，无 contrastive margin）筛选的 2691 样本做 RSFT。对比 CED scoring RSFT（2718 样本）。验证 CED 的对比性 margin 是否是关键因素。如 flat-NLI RSFT ≈ CED RSFT → CED 无增益；如 CED RSFT 显著优于 → contrastive margin 关键。\", \"conclusion\": \"success\"}, \"eval_plan_001_flat_nli\": {\"status\": \"DONE\", \"hypothesis\": \"Dev eval of flat-NLI RSFT (plan_001). 对比 CED RSFT (3-seed mean rel_f1=0.4596). flat-NLI ≈ CED → CED contrastive margin 无增益; CED >> flat-NLI → margin 关键。\", \"conclusion\": \"success\"}, \"eval_grpo_g8_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"Eval GRPO G=8 bf16 checkpoints 80/90/100 on full dev set (985 docs). 验证 catastrophic forgetting 是否在 bf16 LoRA 下复现。rel_f1>0.30 → forgetting 不复现 (QLoRA-specific); rel_f1<0.05 → 复现 (C2 加强)。对比: SFT rel_f1=0.4057, QLoRA GRPO rel_f1=0.2167 (catastrophic).\", \"conclusion\": \"success\"}, \"plan_015_grpo_g4_bf16_v3\": {\"status\": \"DONE\", \"hypothesis\": \"P2 robustness check: bf16 LoRA GRPO G=4, kl=0.01, lr=5e-6。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean single-variable quantization ablation (Δ=+23.8pp)。v3 仅为 robustness data point，lr=5e-6 与对照组 lr=5e-5 不一致。\", \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16_v2\": {\"status\": \"DONE\", \"hypothesis\": \"Robustness check: bf16 LoRA GRPO 在 G=4, kl=0, lr=5e-6 条件下是否也防止 catastrophic forgetting。非 single-variable ablation（kl/lr/G 均与 QLoRA 对照组不同）。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean quantization ablation。\", \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"bf16 LoRA GRPO clean control: 与原始 QLoRA GRPO 仅改 quantization（4-bit → bf16），保持 G=4, kl=0, CED reward 不变。验证 catastrophic forgetting 是否由 QLoRA quantization 导致。\", \"conclusion\": \"killed\"}, \"plan_011_grpo_g8_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO G=8 bf16 LoRA: 验证 catastrophic forgetting 是否在 bf16（非 QLoRA 4-bit）下仍复现。CED reward + kl_coef=0.01, 100 steps。如仍 fail → 加强 Claim 3\", \"conclusion\": \"success\"}, \"plan_011_grpo_g8_bf16_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_004_dreeam_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Phase A: 复现 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1≈54.15, RE-F1≈63.49。论文报告的57.34是student model在test set的结果，需4阶段self-training pipeline。\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b_maxtok1536_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). Retry with correct model stack (Base+SFT+RSFT). If EDCR improves significantly (from 0.6609 toward 0.71+), truncation is the cause. If unchanged, distractor citation is genuine RSFT behavior.\", \"conclusion\": \"negative\"}, \"plan_001_flat_nli_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"flat-NLI scoring 前置步骤：用 flat_nli 模式（p_pos 概率，无 contrastive margin）对 RSFT 生成候选打分并筛选训练数据。\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798. Retry of mvp2_eval_rsft_s43 (fixed arg names).\", \"conclusion\": \"success\"}, \"mvp2_rsft_ced_scoring_topk3_r2\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Retry with HF_HUB_OFFLINE=1 (NLI model cached locally).\", \"conclusion\": \"success\"}, \"mvp2_rsft_train_r1_s44\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT training seed=44 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of r2b (1 epoch, alpha=32, lr=1e-5, clean data). Ablation: conservative LoRA scaling vs r2a/r1. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2a\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of r2a (1 epoch, alpha=128, clean data). Ablation: 1 epoch vs 3 epoch (r1). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r1\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT r1 (seed=42). Same pipeline as s44 eval (985 docs, no-quantize). Need 3-seed data for complete_mvp. s44 PASS: rel_f1=0.4655, evi_f1=0.8087.\", \"conclusion\": \"success\"}, \"mvp2_eval_sft_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline eval using identical eval protocol as GRPO evals (eval_lr5e6_ckpt20.sh). Required for MVP-2 core comparison: CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp. Prior SFT eval (r3) used different eval path; this ensures apple-to-apple comparison.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b_maxtok1536\": {\"status\": \"DONE\", \"hypothesis\": \"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). If EDCR improves significantly (from 0.6609 toward 0.71+), current EDCR gap is truncation artifact, not model issue. If EDCR unchanged, distractor citation is genuine RSFT behavior.\", \"conclusion\": \"killed\"}, \"mvp2_rsft_ced_scoring_topk3\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Answers: does CED filtering strictness affect RSFT training quality?\", \"conclusion\": \"killed\"}, \"mvp2_rsft_r2b\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT r2b: data fix + training dynamics fix (1 epoch + filter truncated + LoRA alpha=32/r=64 scaling 0.5 + lr=1e-5). Isolates: is conservative LoRA scaling the key factor? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_rsft_r2a\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT r2a: data fix only (1 epoch + filter 170 truncated JSON → 2548 samples). Same LoRA alpha=128/r=64, lr=2e-5 as r1. Isolates: does 1 epoch + clean data alone fix the ontology collapse? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_rsft_diagnosis\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT failure root cause: rel_f1=0.0483 vs SFT 0.4057. Diagnose: training data distribution (relation count), step-170 checkpoint output analysis, SFT vs RSFT data comparison.\", \"conclusion\": \"success\"}, \"mvp2_eval_ced_kl001_r4_last\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001_r3\": {\"status\": \"DONE\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr + bash -c wrapping)\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001_r2\": {\"status\": \"DONE\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr → --learning_rate)\", \"conclusion\": \"killed\"}, \"mvp2_rsft_train_r2_fix\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT r2 fix: 4 fixes based on r1 diagnosis. 1) 1 epoch (vs 3), 2) LoRA alpha=32/r=64 (scaling 0.5 vs 2.0), 3) filtered truncated JSON (~2548 vs 2718 samples), 4) lr=1e-5 (vs 2e-5). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"killed\"}, \"mvp2_rsft_train_r1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT training seed=43 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"failed\"}, \"mvp2_rsft_train_r1\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT training on CED-filtered data (2718 samples, mean CED=0.668). SFT warmup baseline: rel_f1=0.4057, evi_f1=0.798. Pass criteria: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_rsft_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring + filtering on 4 shard RSFT generations. top_k=1, f1_threshold=0.1. 21952 → 2718 selected (12.4%).\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s0\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 0/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s3\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 3/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s2\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 2/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s1\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 1/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_generate\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation phase: SFT model generates N=8 candidate outputs per training sample at T=0.7. CED scoring + filtering后作为 RSFT 训练数据。D031 pivot 方向。\", \"conclusion\": \"failed\"}, \"mvp2_diversity_probe\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT viability check: SFT model output diversity at T=0.7/1.0 with N=8 generations. Pass criteria: unique triple-sets >= 5/8.\", \"conclusion\": \"success\"}, \"mvp2_eval_lr5e6_r1_ckpt100\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-100 eval: lr=5e-6 GRPO at step 100 (halfway point). Checkpoint-100 已保存。与 kl001_r4 的 step-100 (rel_f1=0.217) 形成直接对比。Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_grpo_ced_lr5e6_r1\": {\"status\": \"DONE\", \"hypothesis\": \"D030/P0: lr=5e-6 (10x lower than ced_kl001_r4) prevents catastrophic forgetting while maintaining CED reward improvement. Community consensus GRPO+QLoRA lr=5e-6~1e-5. Pass criteria: ckpt-20 rel_f1 > 0.30. Extra monitoring: pred_count + recall trend.\", \"conclusion\": \"killed\"}, \"mvp2_eval_lr5e6_r1_ckpt80\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-80 eval: lr=5e-6 GRPO at step 80. 训练轨迹继续——ckpt-20 FAIL (0.0077), ckpt-40/60 待出. Step 80 reward=0.283 (回升), format_reward=0.249. Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_r1_ckpt60_r2\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-60 eval retry: 原 submit_on_allocated 失败 (pid=unknown). 手动 SSH 启动 /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh. Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_r1_ckpt60\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-60 eval: lr=5e-6 GRPO at step 60. 训练轨迹数据点——ckpt-20 catastrophic forgetting (rel_f1=0.0077)，需看后续 checkpoint 是否恢复。Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"failed\"}, \"mvp2_eval_lr5e6_r1_ckpt40_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Re-tracking orphan PID 101842 for P0 ckpt-40 eval (lr=5e-6 GRPO step 40). Original exp auto-failed due to cron/PID mismatch. Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_r1_ckpt20\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-20 early eval: lr=5e-6 GRPO at step 20. Pass criteria: rel_f1 > 0.30 (no catastrophic forgetting). Key MVP gate for P0.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_rp_r2_ckpt20\": {\"status\": \"DONE\", \"hypothesis\": \"P0+P1 ckpt-20 eval: lr=5e-6 + recall_penalty GRPO at step 20. Director killed rp_r2 training (loss divergence), but ckpt-20 eval needed to close P0+P1 comparison line. Pass criteria: rel_f1 > 0.30 AND pred_count >= 9720.\", \"conclusion\": \"killed\"}, \"mvp2_eval_lr5e6_r1_ckpt40\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-40 eval: lr=5e-6 GRPO at step 40 (where f1_reward first rises to 0.038). Director 新判定框架: ckpt-20 FAIL + ckpt-40 PASS → P0 判 PASS。Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_rp_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D032/P0+P1 retry: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 (lr5e6_r1) isolates CED shortcut fix contribution. Retry of rp_r1 which failed due to bash quoting.\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_multi\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_lr5e6_rp_r1\": {\"status\": \"DONE\", \"hypothesis\": \"D032/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_p1_r1\": {\"status\": \"DONE\", \"hypothesis\": \"D031/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 15000 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_step90\": {\"status\": \"DONE\", \"hypothesis\": \"Eval true best checkpoint (step 90, reward=1.370). Critical after ckpt-50 showed reward hacking (rel_f1 -24.9pp). If step 90 also fails, CED reward design has fundamental issue.\", \"conclusion\": \"negative\"}, \"mvp2_eval_ced_kl001_r4_ckpt7080\": {\"status\": \"DONE\", \"hypothesis\": \"Re-run failed ckpt-70/80 eval from crashed high eval (cuda:3 OOM). Completes 10-checkpoint trajectory for paper negative result analysis.\", \"conclusion\": \"failed\"}, \"mvp2_eval_ced_kl001_r4_high\": {\"status\": \"DONE\", \"hypothesis\": \"High-end checkpoint eval (60,70,80,90) on cuda:3, complementing cuda:2 low-end eval. Step 90 is true best checkpoint (reward=1.370). D024 directive.\", \"conclusion\": \"failed\"}, \"mvp2_eval_ced_kl001_r4_step100\": {\"status\": \"DONE\", \"hypothesis\": \"Eval ced_kl001_r4 last checkpoint (step 100) to compare with best-reward checkpoint (step 50). If best ≠ last, the gap measures training stability under batch_size=1 GRPO variance.\", \"conclusion\": \"negative\"}, \"mvp2_eval_ced_kl001_r4_ckpt90\": {\"status\": \"DONE\", \"hypothesis\": \"Eval ced_kl001_r4 best-reward checkpoint (step 90, reward=1.370, f1=0.720) — this is the primary MVP-2 judgment checkpoint. If evi_f1 ≥ SFT baseline (0.7979) + 2pp = 0.8179, MVP-2 passes.\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_ckpt10\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_eval_ced_kl001_r4_early\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r6\": {\"status\": \"DONE\", \"hypothesis\": \"Flat-NLI reward with kl_coef=0.01 + num_generations=8 from SFT scratch (not resume). 100-step probe to verify stability. Same D020 config as ced_kl001_r4 (which is healthy). Tests whether flat-NLI reward type works under stable training config.\", \"conclusion\": \"negative\"}, \"mvp2_grpo_ced_kl001_r4\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_grpo_extract_r4\": {\"status\": \"DONE\", \"hypothesis\": \"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0.01 + num_generations=8 trains stably. 100-step probe parallel ablation with ced_kl001_r4 (CED reward) to compare reward type impact under identical stability config.\", \"conclusion\": \"killed\"}, \"mvp2_grpo_flatnli_r5\": {\"status\": \"DONE\", \"hypothesis\": \"Flat-NLI reward with kl_coef=0.01 + num_generations=8 prevents mode collapse. Resume from flatnli_r3 checkpoint-100 (healthy). 100-step probe (steps 100→200) to verify stability before full run.\", \"conclusion\": \"killed\"}, \"mvp2_sft_eval_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_grpo_extract_r3\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001\": {\"status\": \"DONE\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r5\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_sft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_flatnli_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_extract_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_extract\": {\"status\": \"DONE\", \"hypothesis\": \"Extraction-only reward (format+F1, no CED) establishes GRPO baseline — CED r3 should exceed this on Evi-F1\", \"conclusion\": \"failed\"}, \"mvp2_grpo_flatnli\": {\"status\": \"DONE\", \"hypothesis\": \"Flat-NLI reward (non-contrastive) improves Evi-F1 over extraction-only but less than CED — validates contrastive component's incremental value\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r3\": {\"status\": \"DONE\", \"hypothesis\": \"CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + stable training (num_iterations=1, KL early stop at 100) + kl_coef=0.05 improves Evi-F1 over SFT baseline\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_r1\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"precompute_nli_train\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_sft_warmup\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"smoke_test_grpo\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp1_ced_signal\": {\"status\": \"DONE\", \"conclusion\": \"success\"}}, \"count\": 237, \"total\": 237, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7213}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 12_

<details><summary>Logged reasoning block</summary>

```text
The experiment_plan.yaml is not in the whitelist for read_project_file. I need to find it on disk. Let me check the project directory structure.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "4fe923bc-ee6b-4c6d-8604-5e0e3e709bc0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UV1FvvScj7xQU98uuhUDN2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1647,
      "cache_read_input_tokens": 26183,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1647
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 13_

experiment_plan.yaml 不在 read_project_file 白名单中。让我直接从磁盘读取。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "4ce7430f-f28d-4455-a511-e4a50d5a635c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UV1FvvScj7xQU98uuhUDN2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1647,
      "cache_read_input_tokens": 26183,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1647
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Glob · `toolu_018RNQU1VYtC1L3UQJyMcrQX`</summary>

```json
{
  "pattern": "**/experiment_plan.yaml",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "40606866-1f52-4faa-ab8e-291d70099755",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UV1FvvScj7xQU98uuhUDN2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1647,
      "cache_read_input_tokens": 26183,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1647
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-19T05:44:17.155Z_

<details><summary>↩ Tool result · `toolu_018RNQU1VYtC1L3UQJyMcrQX`</summary>

```text
experiment_plan.yaml
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "0681c68c-7eac-45af-9064-2e935a76ca4a",
  "tool_use_result": {
    "filenames": [
      "experiment_plan.yaml"
    ],
    "durationMs": 60,
    "numFiles": 1,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Read · `toolu_01X67UJUcQ6n9TX65o9ecRP4`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/634a5108-09f6-4d84-84f8-5d5a864789c4/tool-results/toolu_01UKhBf9ZzfmDkWYfqZNB2Zu.txt"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "fea5d5af-16ec-46ec-bac8-56a7223708ff",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UV1FvvScj7xQU98uuhUDN2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1647,
      "cache_read_input_tokens": 26183,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1647
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 17 · 2026-05-19T05:44:21.018Z_

<details><summary>↩ Tool result · `toolu_01X67UJUcQ6n9TX65o9ecRP4`</summary>

```text
1	{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan019_1_7b_rsft_s44_r2\": {\"status\": \"RUNNING\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\"}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"RUNNING\", \"hypothesis\": \"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"success\"}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"failed\"}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\", \"conclusion\": \"failed\"}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_train\": {\"status\": \"RUNNING\", \"hypothesis\": \"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\"}, \"plan017_14b_sft\": {\"status\": \"RUNNING\"}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"hypothesis\": \"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard3\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard1\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard2\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard0\": {\"status\": \"DONE\", \"hypothesis\": \"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\", \"conclusion\": \"success\"}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"hypothesis\": \"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\", \"conclusion\": \"killed\"}, \"plan019_8b_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\", \"conclusion\": \"success\"}, \"plan019_8b_sft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\", \"conclusion\": \"success\"}, \"grpo_bf16_g4_ckpt200_eval\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\", \"conclusion\": \"success\"}, \"random_rsft_k1_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s44_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s43_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\", \"conclusion\": \"success\"}, \"plan019_8b_sft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\", \"conclusion\": \"success\"}, \"wave1_grpo_bf16_g4\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\", \"conclusion\": \"success\"}, \"random_rsft_k1_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\", \"conclusion\": \"success\"}, \"grpo_bf16_g4_ckpt100_eval\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\", \"conclusion\": \"failed\"}, \"wave1_sft_4b_s44_eval\": {\"status\": \"DONE\", \"hypothesis\": \"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"conclusion\": \"failed\"}, \"wave1_sft_4b_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"SFT 4B seed43 eval (D076 protocol): baseline SFT performance for seed43. Paired with s44 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\", \"conclusion\": \"failed\"}, \"seed_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s44\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline for Qwen3-4B seed44: second seed for SFT baseline. Paired with seed43 for mean±std reporting. Expected rel_f1 similar to seed43 (~50.5±1pp).\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s43\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline for Qwen3-4B seed43: standard SFT without CED filtering. Paired with RSFT to measure CED filtering gain. Expected rel_f1 ~50.5 based on prior 8B SFT results scaled down.\", \"conclusion\": \"success\"}, \"d102_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\", \"conclusion\": \"killed\"}, \"seed_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_llama_k1_s43_train\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。\", \"conclusion\": \"success\"}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\", \"conclusion\": \"success\"}, \"d102_8b_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3018 samples vs 9041），预期 rel_f1 与 k=3 相当或略有变化，验证 k=1 在 8B 上同样有效。\", \"conclusion\": \"success\"}, \"d102_llama_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。\", \"conclusion\": \"success\"}, \"d102_1_7b_rsft_k1_s42\": {\"status\": \"DONE\", \"hypothesis\": \"D102 方法论修正：1.7B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3021 samples vs 9042），在最小模型上验证 k=1 RSFT 效果。\", \"conclusion\": \"success\"}, \"seed_comparison_prep\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan006_1_7b_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_s43_dev_eval_preds\": {\"status\": \"DONE\", \"hypothesis\": \"Eval RSFT-s43 (CED-scored) on DocRED dev with predictions saved. Prerequisite for Lead 1 CED evidence filtering: per-sentence NLI scoring requires full prediction outputs.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT model (checkpoint-1698) on DocRED dev. Retry after disk-full crash. Validates CED-filtered RSFT at smallest model scale in scaling study.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_r3_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data (9041 samples) on Qwen3-8B, resume from checkpoint-750 after disk-full crash. At 8B scale, CED-filtered RSFT should achieve highest absolute performance in scaling study.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_seed43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5219. If seed 43 gives similar result (±1pp, i.e., 0.51-0.53), the 1.7B scaling study datapoint is robust.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate 1.7B RSFT test set predictions for CodaLab submission. 1.7B RSFT dev rel_f1=0.5219, expect similar performance on test.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate 8B RSFT test set predictions for CodaLab submission. 8B RSFT dev rel_f1=0.5606, expect similar performance on test.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43_eval_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust against seed variance.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_test\": {\"status\": \"DONE\", \"hypothesis\": \"Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43\": {\"status\": \"DONE\", \"hypothesis\": \"Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed variance.\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.\", \"conclusion\": \"failed\"}, \"lead2_ckpt20_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate GRPO checkpoint-20 from RSFT base (lead2_rsft_grpo_ced_r2) on DocRED dev. If RSFT→GRPO preserves/improves rel_f1 over RSFT baseline (0.4601), it validates the RSFT→GRPO training pipeline as viable.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate Qwen3-8B RSFT (CED-scored data, 9041 samples) on DocRED dev. At 8B scale with near-zero evidence tax, CED-RSFT should achieve highest absolute Ign-F1 in the scaling study.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_seed43\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with seed 43 on Qwen3-1.7B will produce comparable performance to other seeds, validating seed robustness for the scaling study\", \"conclusion\": \"success\"}, \"post_hoc_bm25_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Post-hoc BM25 evidence retrieval on SFT-no-evidence predictions: if retrieving evidence after RE produces comparable joint Evi-F1 and EDCR to jointly trained RSFT, then joint generation is unnecessary. Expect RSFT to have better evidence quality (lower EDCR) due to training-time evidence grounding.\", \"conclusion\": \"success\"}, \"lead1_ced_evidence_filter\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"hypothesis\": \"Post-hoc CED-based evidence filtering on RSFT predictions: removing low-NLI-score evidence sentences at inference time should improve Evi-F1 and EDCR by eliminating distractor citations, without affecting rel_f1.\"}, \"plan_006_qwen3_8b_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data (9041 samples) on Qwen3-8B will improve rel_f1 over SFT baseline. At 8B scale with near-zero evidence tax, CED-filtered RSFT should achieve the highest absolute performance in the model scaling study.\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_rsft_eval\": {\"status\": \"DONE\", \"hypothesis\": \"Evaluate 1.7B RSFT model on DocRED dev to measure rel_f1 improvement over SFT baseline. Validates that CED-filtered RSFT generalizes to smallest model scale (1.7B) in the scaling study.\", \"conclusion\": \"failed\"}, \"rsft_s44_dev_eval_preds\": {\"status\": \"DONE\", \"hypothesis\": \"Re-run RSFT s44 dev eval with predictions saved, as prerequisite for CED evidence filtering experiment (线索1: inference-time distractor citation removal). Predictions needed for per-sentence NLI scoring.\", \"conclusion\": \"failed\"}, \"lead2_rsft_grpo_ced_r2\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT→bf16 GRPO two-stage (retry with --data_dir fix): starting from merged RSFT-s43 checkpoint (rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should improve evidence quality (EDCR) while preserving rel_f1.\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_train_r3\": {\"status\": \"DONE\", \"hypothesis\": \"bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues seen in r1/r2 attempts\", \"conclusion\": \"success\"}, \"lead2_rsft_grpo_ced\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT→bf16 GRPO two-stage: starting from RSFT best checkpoint (s43, rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should further improve evidence quality (EDCR) while preserving rel_f1, because RSFT provides stable base preventing catastrophic forgetting seen in SFT→GRPO.\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_8b_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring on Qwen3-8B RSFT candidates (24216 gens from 3027 docs) will produce high-quality filtered training data. At 8B scale with near-zero evidence tax, CED-filtered RSFT should yield further gains over an already strong SFT baseline.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT with CED-scored data on Qwen3-1.7B will improve relation extraction F1 over SFT baseline by selectively reinforcing high-quality extraction patterns, similar to gains seen on 4B model\", \"conclusion\": \"success\"}, \"plan_002_test_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT-CED s44 (best dev config, rel_f1=0.4655) maintains improvement over SFT on held-out test set, confirming CED-filtered rejection sampling gains are not dev-set overfitting. Test Ign-F1 should exceed SFT test baseline.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_candidates_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Resuming 8B candidate generation from idx 2701 will complete the full RSFT candidate set needed for reward-based filtering and RSFT training\", \"conclusion\": \"success\"}, \"plan_016_llama_rsft_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_train\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families (Qwen→LLaMA).\", \"conclusion\": \"failed\"}, \"plan_016_llama_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring (NLI contrastive discrimination) can effectively filter 1.7B model candidates despite lower generation quality: NLI-based selection should identify high-quality evidence samples even from a capacity-limited generator.\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"hypothesis\": \"CED-RSFT improvements on DocRED should transfer to Re-DocRED: RSFT model should outperform SFT baseline on Re-DocRED Ign-F1, demonstrating cross-dataset generalization of rejection sampling gains.\"}, \"plan_006_qwen3_1_7b_rsft_candidates\": {\"status\": \"DONE\", \"hypothesis\": \"Qwen3-1.7B RSFT candidate generation (N=8, T=0.7). Scale ablation: smallest model RSFT candidates for CED scoring. plan_006 claim=3.\", \"conclusion\": \"success\"}, \"plan_002_test_eval_s44_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"DocRED test set evaluation for RSFT-CED s44 (best dev config). Final benchmark numbers for paper submission; test set performance confirms dev set gains are not overfitting artifacts.\"}, \"plan_006_qwen3_8b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-8B no-evidence SFT baseline for evidence tax measurement at 8B scale. If 8B no-evi rel_f1 ≈ 8B evidence-SFT rel_f1, confirms that 8B absorbs evidence cost (tax≈0).\"}, \"plan_006_qwen3_1_7b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-1.7B no-evidence SFT baseline for evidence tax measurement at 1.7B scale. Paired with evidence-SFT to quantify whether evidence generation constrains or helps small model RE performance.\"}, \"plan_006_qwen3_1_7b_sft_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-1.7B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: smallest model expected to show highest evidence tax due to capacity-constrained multi-task optimization.\"}, \"plan_006_qwen3_8b_sft_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-8B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: larger model should achieve higher rel_f1 than 4B (0.4057) and 1.7B baselines, with lower evidence tax due to greater capacity.\"}, \"reeval_sft_baseline_d076\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Re-eval Qwen3-4B SFT baseline under D076 unified protocol (batch_size=4, no-quantize, max_new_tokens=1024, seed=42). Required as canonical comparison point for all RSFT/GRPO experiments and evidence tax computation.\"}, \"plan_006_qwen3_1_7b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-1.7B evidence-SFT eval under D076 protocol. Establishes smallest-scale SFT baseline; evidence tax at 1.7B predicted negative (evidence helps small models by constraining over-prediction).\"}, \"plan_006_qwen3_8b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"Qwen3-8B evidence-SFT eval under D076 unified protocol. Establishes 8B-scale SFT baseline for evidence tax measurement (paired with no-evidence eval) and RSFT improvement quantification.\"}, \"plan_016_llama_3_1_8b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B no-evidence SFT baseline for cross-family evidence tax measurement. Paired with evidence-SFT to quantify evidence generation cost on a non-Qwen architecture at 8B scale.\"}, \"plan_016_llama_3_1_8b_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B can be SFT-trained for evidence-grounded DocRE with the same pipeline as Qwen3 family, enabling cross-family generalization claims for the FREIGE framework.\"}, \"plan_007_redocred_4b_sft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"FREIGE SFT model trained on DocRED transfers to Re-DocRED without re-training: if Ign-F1 drop <5pp and Evi-F1 maintains, the learned evidence grounding generalizes across annotation schemes.\"}, \"plan_006_qwen3_8b_no_evidence_eval_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"8B model capacity absorbs evidence generation cost: no-evidence SFT and evidence-SFT should produce near-identical rel_f1, demonstrating evidence tax≈0 at 8B scale (contrasting with 4B where tax=-7.5pp).\"}, \"plan_016_llama_3_1_8b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B no-evidence SFT should achieve similar rel_f1 to evidence-SFT (tax≈0), cross-family validating the 8B-scale evidence absorption pattern observed in Qwen3-8B.\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"1.7B model capacity is insufficient to jointly optimize RE and evidence generation: no-evidence SFT should outperform evidence-SFT on rel_f1, revealing positive evidence tax at small scale (opposite to 8B where tax≈0).\"}, \"plan_016_llama_3_1_8b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"LLaMA-3.1-8B SFT with evidence generation should achieve comparable rel_f1 to Qwen3-8B SFT, establishing cross-family baseline for evidence tax measurement. Evidence tax at 8B scale predicted near-zero based on Qwen3-8B pattern.\"}, \"plan_016_llama_grpo_qlora\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"hypothesis\": \"QLoRA GRPO catastrophic decoupling (format gaming + zero IE ability) is not Qwen-specific: LLaMA-3.1-8B under identical QLoRA GRPO training should exhibit the same failure mode (grad_norm→0, loss→0, rel_f1→0). Cross-family validation of C2.\"}, \"plan_006_qwen3_8b_rsft_candidates\": {\"status\": \"DONE\", \"hypothesis\": \"Qwen3-8B RSFT candidate generation (N=8, T=0.7). Generates rejection sampling candidates for subsequent CED scoring and filtering. plan_006 claim=3.\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_candidates_r3\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT candidate gen r3 (N=8, T=0.7, start_idx=64 resume). Exclusive cuda:2 after GRPO kill.\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r5\": {\"status\": \"DONE\", \"hypothesis\": \"CED-RSFT gains transfer to Re-DocRED (r5, correct 3-param loading: base→SFT→RSFT)\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r4\": {\"status\": \"DONE\", \"hypothesis\": \"CED-RSFT gains transfer to Re-DocRED (r4, correct 3-param loading: base→SFT→RSFT)\", \"conclusion\": \"failed\"}, \"plan_002_test_rsft_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_007_redocred_rsft_eval_r3\": {\"status\": \"DONE\", \"hypothesis\": \"Re-DocRED RSFT eval r3 (config fix: model_path=base, sft_adapter=RSFT ckpt). Verify CED-RSFT gains transfer cross-dataset.\", \"conclusion\": \"failed\"}, \"plan_007_redocred_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_014_no_evidence_eval_d076\": {\"status\": \"DONE\", \"hypothesis\": \"4B no-evidence SFT eval under D076 unified protocol (batch_size=4, max_new_tokens=1024, seed=42, no-quantize). Required for clean scaling comparison across 1.7B/4B/8B.\", \"conclusion\": \"success\"}, \"plan_016_llama_rsft_candidates_r2\": {\"status\": \"DONE\", \"hypothesis\": \"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_candidates\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"hypothesis\": \"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\"}, \"plan_007_redocred_4b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v2r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_8b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s42\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval flat-NLI RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 eval_plan_001_flat_nli 用了 batch_size=16。Paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"reeval_ced_s44\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval CED RSFT s44 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + seed=44. 原 eval 用了 batch_size≈16 且 seed=42（错误）。Paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"reeval_ced_s42\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 mvp2_eval_rsft_r2b_maxtok1536_r2 用了 batch_size=8 + max_new_tokens=1536。Paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"reeval_flat_nli_s44\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan_006_qwen3_1_7b_sft\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval flat-NLI RSFT s43 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + --max_new_tokens 1024. 原 reeval_flat_nli_s43 用了 batch_size=16 导致协议不一致。C3 paired t-test 关键路径。\", \"conclusion\": \"success\"}, \"eval_rsft_ced_s45\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"success\"}, \"eval_rsft_ced_s43\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of CED RSFT seed=43 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 4 个 seed。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"success\"}, \"eval_plan_014_no_evidence_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Retry of eval_plan_014_no_evidence with corrected command: --model_path 传底座 Qwen3-4B, --sft_adapter 传 SFT no-evidence adapter。修复 adapter 检测逻辑冲突。plan_id=plan_014, claim=1。\", \"conclusion\": \"success\"}, \"mvp2_ced_reranker_poc\": {\"status\": \"DONE\", \"hypothesis\": \"CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.\", \"conclusion\": \"success\"}, \"eval_flat_nli_seed45\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。\", \"conclusion\": \"success\"}, \"eval_flat_nli_s44\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。\", \"conclusion\": \"success\"}, \"rsft_ced_s45_train_r4\": {\"status\": \"DONE\", \"hypothesis\": \"CED RSFT seed=45 训练（r4 重试，r3 因 cuda:2 orphan PID 276148 OOM 失败）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44，s43 在 cuda:1 训练中）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"success\"}, \"rsft_ced_s43_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_plan_014_no_evidence\": {\"status\": \"DONE\", \"hypothesis\": \"Dev set eval of SFT-no-evidence model (plan_014). 核心目标：对比标准 SFT rel_f1=0.4057 vs 不输出 evidence 的 SFT rel_f1（隔离 evidence generation 代价）。只评估 rel_f1，不评估 evi_f1（输出无 evidence）。plan_id=plan_014, claim=1。\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_ced_s43_train_r2\": {\"status\": \"DONE\", \"hypothesis\": \"CED RSFT seed=43 训练（r2 重试，修正 cwd 错误）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"conclusion\": \"failed\"}, \"reeval_rsft_topk3\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval RSFT top_k=3 WITH --sft_adapter (D064 bug fix). 原 eval_plan_008_rsft_topk3 因缺 --sft_adapter 被 killed。对比 CED RSFT top_k=1 (rel_f1≈0.46) 和 SFT baseline (0.4057)。\", \"conclusion\": \"negative\"}, \"rsft_ced_s43_train\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s43\": {\"status\": \"DONE\", \"hypothesis\": \"Re-eval flat-NLI RSFT seed=43 WITH --sft_adapter (D064 bug fix). 原 eval_plan_001_flat_nli_s43 因缺 --sft_adapter 导致 rel_f1=0.0022 无效。对比 flat-NLI s42 (rel_f1=0.4539) 和 CED RSFT mean (0.4596)。\", \"conclusion\": \"success\"}, \"plan_003_edcr_diagnostic\": {\"status\": \"DONE\", \"hypothesis\": \"EDCR cross-method diagnostic table: 计算所有 evidence-producing 方法（SFT baseline, RSFT-CED best, RSFT-flatNLI best, CED-reranker）的 EDCR，验证 EDCR 作为独立评估指标的诊断能力。plan_id=plan_003, claim=4。GPU 预算 2h。\", \"conclusion\": \"success\"}, \"eval_flat_nli_seed44\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.\", \"conclusion\": \"killed\"}, \"eval_plan_012_dpo_1ep_fixed_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"plan_001_flat_nli_seed44\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_009_dynamics_figure\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO forgetting dynamics 3-panel figure: QLoRA vs BF16 GRPO 的 rel_f1/evi_f1/EDCR 训练轨迹对比。支撑 Claim 3 (task decoupling 是 QLoRA-specific)。plan_id=plan_009。\", \"conclusion\": \"success\"}, \"plan_001_flat_nli_seed45\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_011_bf16_g8_step_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_011_eval_g8_bf16_ckpt100\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_rsft_s44\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT seed=44 checkpoint. First MVP-2 judgement data point. Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798 (SFT baseline).\", \"conclusion\": \"killed\"}, \"eval_plan_008_topk3_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_012_dpo_1ep_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_008_rsft_topk3\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"hypothesis\": \"RSFT top_k=3 dev eval: 对比 top_k=1 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1≈0.4057)。验证更多候选是否提升证据质量。\"}, \"plan_012_dpo_ced\": {\"status\": \"DONE\", \"hypothesis\": \"DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。\", \"conclusion\": \"negative\"}, \"plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"hypothesis\": \"DPO+CED 1 epoch retraining: plan_012_dpo_ced 3 epochs 严重过拟合 (rewards_accuracy=1.0, margins 9x膨胀, entropy崩塌)。重训 1 epoch 验证 early stopping 是否消除 overfitting confound。对比 plan_012 3ep + RSFT (rel_f1=0.46) + SFT baseline (rel_f1=0.4057)。\", \"conclusion\": \"negative\"}, \"eval_plan_001_flat_nli_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"plan_008_rsft_topk3\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT top_k=3 训练：用 CED-filtered 的 top-3 候选进行 rejection sampling fine-tuning，验证更多候选是否比 top_k=1 (rel_f1≈0.46) 带来更好的证据质量。\", \"conclusion\": \"success\"}, \"plan_001_flat_nli_seed43\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_009_flatnli_reward_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_009_extract_reward_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_sft_baseline_noquant\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_009_flatnli_reward_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_plan_012_dpo_ced_ckpt400\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_009_forgetting_figure\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"hypothesis\": \"SFT-without-evidence ablation: 训练只输出 relation triples（不含 evidence sentences）的 SFT 模型。量化 joint evidence generation 对 extraction 的代价（当前 rel_f1=0.4057 vs 只抽关系的 LMRC 60.7 的 gap 有多少来自 evidence 负担）。\", \"conclusion\": \"success\"}, \"plan_002_test_eval_s44\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_001_rsft_flat_nli\": {\"status\": \"DONE\", \"hypothesis\": \"flat-NLI RSFT ablation: 用 flat-NLI scoring（p_pos 概率，无 contrastive margin）筛选的 2691 样本做 RSFT。对比 CED scoring RSFT（2718 样本）。验证 CED 的对比性 margin 是否是关键因素。如 flat-NLI RSFT ≈ CED RSFT → CED 无增益；如 CED RSFT 显著优于 → contrastive margin 关键。\", \"conclusion\": \"success\"}, \"eval_plan_001_flat_nli\": {\"status\": \"DONE\", \"hypothesis\": \"Dev eval of flat-NLI RSFT (plan_001). 对比 CED RSFT (3-seed mean rel_f1=0.4596). flat-NLI ≈ CED → CED contrastive margin 无增益; CED >> flat-NLI → margin 关键。\", \"conclusion\": \"success\"}, \"eval_grpo_g8_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"Eval GRPO G=8 bf16 checkpoints 80/90/100 on full dev set (985 docs). 验证 catastrophic forgetting 是否在 bf16 LoRA 下复现。rel_f1>0.30 → forgetting 不复现 (QLoRA-specific); rel_f1<0.05 → 复现 (C2 加强)。对比: SFT rel_f1=0.4057, QLoRA GRPO rel_f1=0.2167 (catastrophic).\", \"conclusion\": \"success\"}, \"plan_015_grpo_g4_bf16_v3\": {\"status\": \"DONE\", \"hypothesis\": \"P2 robustness check: bf16 LoRA GRPO G=4, kl=0.01, lr=5e-6。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean single-variable quantization ablation (Δ=+23.8pp)。v3 仅为 robustness data point，lr=5e-6 与对照组 lr=5e-5 不一致。\", \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16_v2\": {\"status\": \"DONE\", \"hypothesis\": \"Robustness check: bf16 LoRA GRPO 在 G=4, kl=0, lr=5e-6 条件下是否也防止 catastrophic forgetting。非 single-variable ablation（kl/lr/G 均与 QLoRA 对照组不同）。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean quantization ablation。\", \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"bf16 LoRA GRPO clean control: 与原始 QLoRA GRPO 仅改 quantization（4-bit → bf16），保持 G=4, kl=0, CED reward 不变。验证 catastrophic forgetting 是否由 QLoRA quantization 导致。\", \"conclusion\": \"killed\"}, \"plan_011_grpo_g8_bf16\": {\"status\": \"DONE\", \"hypothesis\": \"GRPO G=8 bf16 LoRA: 验证 catastrophic forgetting 是否在 bf16（非 QLoRA 4-bit）下仍复现。CED reward + kl_coef=0.01, 100 steps。如仍 fail → 加强 Claim 3\", \"conclusion\": \"success\"}, \"plan_011_grpo_g8_bf16_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_004_dreeam_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"Phase A: 复现 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1≈54.15, RE-F1≈63.49。论文报告的57.34是student model在test set的结果，需4阶段self-training pipeline。\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b_maxtok1536_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). Retry with correct model stack (Base+SFT+RSFT). If EDCR improves significantly (from 0.6609 toward 0.71+), truncation is the cause. If unchanged, distractor citation is genuine RSFT behavior.\", \"conclusion\": \"negative\"}, \"plan_001_flat_nli_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"flat-NLI scoring 前置步骤：用 flat_nli 模式（p_pos 概率，无 contrastive margin）对 RSFT 生成候选打分并筛选训练数据。\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_s43_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798. Retry of mvp2_eval_rsft_s43 (fixed arg names).\", \"conclusion\": \"success\"}, \"mvp2_rsft_ced_scoring_topk3_r2\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Retry with HF_HUB_OFFLINE=1 (NLI model cached locally).\", \"conclusion\": \"success\"}, \"mvp2_rsft_train_r1_s44\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT training seed=44 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of r2b (1 epoch, alpha=32, lr=1e-5, clean data). Ablation: conservative LoRA scaling vs r2a/r1. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2a\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of r2a (1 epoch, alpha=128, clean data). Ablation: 1 epoch vs 3 epoch (r1). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r1\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT r1 (seed=42). Same pipeline as s44 eval (985 docs, no-quantize). Need 3-seed data for complete_mvp. s44 PASS: rel_f1=0.4655, evi_f1=0.8087.\", \"conclusion\": \"success\"}, \"mvp2_eval_sft_baseline\": {\"status\": \"DONE\", \"hypothesis\": \"SFT baseline eval using identical eval protocol as GRPO evals (eval_lr5e6_ckpt20.sh). Required for MVP-2 core comparison: CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp. Prior SFT eval (r3) used different eval path; this ensures apple-to-apple comparison.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b_maxtok1536\": {\"status\": \"DONE\", \"hypothesis\": \"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). If EDCR improves significantly (from 0.6609 toward 0.71+), current EDCR gap is truncation artifact, not model issue. If EDCR unchanged, distractor citation is genuine RSFT behavior.\", \"conclusion\": \"killed\"}, \"mvp2_rsft_ced_scoring_topk3\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Answers: does CED filtering strictness affect RSFT training quality?\", \"conclusion\": \"killed\"}, \"mvp2_rsft_r2b\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT r2b: data fix + training dynamics fix (1 epoch + filter truncated + LoRA alpha=32/r=64 scaling 0.5 + lr=1e-5). Isolates: is conservative LoRA scaling the key factor? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_rsft_r2a\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT r2a: data fix only (1 epoch + filter 170 truncated JSON → 2548 samples). Same LoRA alpha=128/r=64, lr=2e-5 as r1. Isolates: does 1 epoch + clean data alone fix the ontology collapse? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_rsft_diagnosis\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT failure root cause: rel_f1=0.0483 vs SFT 0.4057. Diagnose: training data distribution (relation count), step-170 checkpoint output analysis, SFT vs RSFT data comparison.\", \"conclusion\": \"success\"}, \"mvp2_eval_ced_kl001_r4_last\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001_r3\": {\"status\": \"DONE\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr + bash -c wrapping)\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001_r2\": {\"status\": \"DONE\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr → --learning_rate)\", \"conclusion\": \"killed\"}, \"mvp2_rsft_train_r2_fix\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT r2 fix: 4 fixes based on r1 diagnosis. 1) 1 epoch (vs 3), 2) LoRA alpha=32/r=64 (scaling 0.5 vs 2.0), 3) filtered truncated JSON (~2548 vs 2718 samples), 4) lr=1e-5 (vs 2e-5). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"killed\"}, \"mvp2_rsft_train_r1_s43\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT training seed=43 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_eval_rsft_s43\": {\"status\": \"DONE\", \"hypothesis\": \"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"failed\"}, \"mvp2_rsft_train_r1\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT training on CED-filtered data (2718 samples, mean CED=0.668). SFT warmup baseline: rel_f1=0.4057, evi_f1=0.798. Pass criteria: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"conclusion\": \"success\"}, \"mvp2_rsft_ced_scoring\": {\"status\": \"DONE\", \"hypothesis\": \"CED scoring + filtering on 4 shard RSFT generations. top_k=1, f1_threshold=0.1. 21952 → 2718 selected (12.4%).\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s0\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 0/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s3\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 3/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s2\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 2/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s1\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation shard 1/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"conclusion\": \"success\"}, \"mvp2_rsft_generate\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT generation phase: SFT model generates N=8 candidate outputs per training sample at T=0.7. CED scoring + filtering后作为 RSFT 训练数据。D031 pivot 方向。\", \"conclusion\": \"failed\"}, \"mvp2_diversity_probe\": {\"status\": \"DONE\", \"hypothesis\": \"RSFT viability check: SFT model output diversity at T=0.7/1.0 with N=8 generations. Pass criteria: unique triple-sets >= 5/8.\", \"conclusion\": \"success\"}, \"mvp2_eval_lr5e6_r1_ckpt100\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-100 eval: lr=5e-6 GRPO at step 100 (halfway point). Checkpoint-100 已保存。与 kl001_r4 的 step-100 (rel_f1=0.217) 形成直接对比。Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_grpo_ced_lr5e6_r1\": {\"status\": \"DONE\", \"hypothesis\": \"D030/P0: lr=5e-6 (10x lower than ced_kl001_r4) prevents catastrophic forgetting while maintaining CED reward improvement. Community consensus GRPO+QLoRA lr=5e-6~1e-5. Pass criteria: ckpt-20 rel_f1 > 0.30. Extra monitoring: pred_count + recall trend.\", \"conclusion\": \"killed\"}, \"mvp2_eval_lr5e6_r1_ckpt80\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-80 eval: lr=5e-6 GRPO at step 80. 训练轨迹继续——ckpt-20 FAIL (0.0077), ckpt-40/60 待出. Step 80 reward=0.283 (回升), format_reward=0.249. Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_r1_ckpt60_r2\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-60 eval retry: 原 submit_on_allocated 失败 (pid=unknown). 手动 SSH 启动 /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh. Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_r1_ckpt60\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-60 eval: lr=5e-6 GRPO at step 60. 训练轨迹数据点——ckpt-20 catastrophic forgetting (rel_f1=0.0077)，需看后续 checkpoint 是否恢复。Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"failed\"}, \"mvp2_eval_lr5e6_r1_ckpt40_r2\": {\"status\": \"DONE\", \"hypothesis\": \"Re-tracking orphan PID 101842 for P0 ckpt-40 eval (lr=5e-6 GRPO step 40). Original exp auto-failed due to cron/PID mismatch. Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_r1_ckpt20\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-20 early eval: lr=5e-6 GRPO at step 20. Pass criteria: rel_f1 > 0.30 (no catastrophic forgetting). Key MVP gate for P0.\", \"conclusion\": \"negative\"}, \"mvp2_eval_lr5e6_rp_r2_ckpt20\": {\"status\": \"DONE\", \"hypothesis\": \"P0+P1 ckpt-20 eval: lr=5e-6 + recall_penalty GRPO at step 20. Director killed rp_r2 training (loss divergence), but ckpt-20 eval needed to close P0+P1 comparison line. Pass criteria: rel_f1 > 0.30 AND pred_count >= 9720.\", \"conclusion\": \"killed\"}, \"mvp2_eval_lr5e6_r1_ckpt40\": {\"status\": \"DONE\", \"hypothesis\": \"P0 ckpt-40 eval: lr=5e-6 GRPO at step 40 (where f1_reward first rises to 0.038). Director 新判定框架: ckpt-20 FAIL + ckpt-40 PASS → P0 判 PASS。Pass criteria: rel_f1 > 0.30.\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_rp_r2\": {\"status\": \"DONE\", \"hypothesis\": \"D032/P0+P1 retry: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 (lr5e6_r1) isolates CED shortcut fix contribution. Retry of rp_r1 which failed due to bash quoting.\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_multi\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_lr5e6_rp_r1\": {\"status\": \"DONE\", \"hypothesis\": \"D032/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_p1_r1\": {\"status\": \"DONE\", \"hypothesis\": \"D031/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 15000 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_step90\": {\"status\": \"DONE\", \"hypothesis\": \"Eval true best checkpoint (step 90, reward=1.370). Critical after ckpt-50 showed reward hacking (rel_f1 -24.9pp). If step 90 also fails, CED reward design has fundamental issue.\", \"conclusion\": \"negative\"}, \"mvp2_eval_ced_kl001_r4_ckpt7080\": {\"status\": \"DONE\", \"hypothesis\": \"Re-run failed ckpt-70/80 eval from crashed high eval (cuda:3 OOM). Completes 10-checkpoint trajectory for paper negative result analysis.\", \"conclusion\": \"failed\"}, \"mvp2_eval_ced_kl001_r4_high\": {\"status\": \"DONE\", \"hypothesis\": \"High-end checkpoint eval (60,70,80,90) on cuda:3, complementing cuda:2 low-end eval. Step 90 is true best checkpoint (reward=1.370). D024 directive.\", \"conclusion\": \"failed\"}, \"mvp2_eval_ced_kl001_r4_step100\": {\"status\": \"DONE\", \"hypothesis\": \"Eval ced_kl001_r4 last checkpoint (step 100) to compare with best-reward checkpoint (step 50). If best ≠ last, the gap measures training stability under batch_size=1 GRPO variance.\", \"conclusion\": \"negative\"}, \"mvp2_eval_ced_kl001_r4_ckpt90\": {\"status\": \"DONE\", \"hypothesis\": \"Eval ced_kl001_r4 best-reward checkpoint (step 90, reward=1.370, f1=0.720) — this is the primary MVP-2 judgment checkpoint. If evi_f1 ≥ SFT baseline (0.7979) + 2pp = 0.8179, MVP-2 passes.\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_ckpt10\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_eval_ced_kl001_r4_early\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r6\": {\"status\": \"DONE\", \"hypothesis\": \"Flat-NLI reward with kl_coef=0.01 + num_generations=8 from SFT scratch (not resume). 100-step probe to verify stability. Same D020 config as ced_kl001_r4 (which is healthy). Tests whether flat-NLI reward type works under stable training config.\", \"conclusion\": \"negative\"}, \"mvp2_grpo_ced_kl001_r4\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_grpo_extract_r4\": {\"status\": \"DONE\", \"hypothesis\": \"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0.01 + num_generations=8 trains stably. 100-step probe parallel ablation with ced_kl001_r4 (CED reward) to compare reward type impact under identical stability config.\", \"conclusion\": \"killed\"}, \"mvp2_grpo_flatnli_r5\": {\"status\": \"DONE\", \"hypothesis\": \"Flat-NLI reward with kl_coef=0.01 + num_generations=8 prevents mode collapse. Resume from flatnli_r3 checkpoint-100 (healthy). 100-step probe (steps 100→200) to verify stability before full run.\", \"conclusion\": \"killed\"}, \"mvp2_sft_eval_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_grpo_extract_r3\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001\": {\"status\": \"DONE\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r5\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_sft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_flatnli_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_extract_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_extract\": {\"status\": \"DONE\", \"hypothesis\": \"Extraction-only reward (format+F1, no CED) establishes GRPO baseline — CED r3 should exceed this on Evi-F1\", \"conclusion\": \"failed\"}, \"mvp2_grpo_flatnli\": {\"status\": \"DONE\", \"hypothesis\": \"Flat-NLI reward (non-contrastive) improves Evi-F1 over extraction-only but less than CED — validates contrastive component's incremental value\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r3\": {\"status\": \"DONE\", \"hypothesis\": \"CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + stable training (num_iterations=1, KL early stop at 100) + kl_coef=0.05 improves Evi-F1 over SFT baseline\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_r1\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"precompute_nli_train\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_sft_warmup\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"smoke_test_grpo\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp1_ced_signal\": {\"status\": \"DONE\", \"conclusion\": \"success\"}}, \"count\": 237, \"total\": 237, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7213}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "8893926b-ce65-4e67-8c5e-2f3447ac76fc",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/634a5108-09f6-4d84-84f8-5d5a864789c4/tool-results/toolu_01UKhBf9ZzfmDkWYfqZNB2Zu.txt",
      "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"plan019_1_7b_rsft_s44_r2\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s44 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\"}, \\\"plan019_1_7b_rsft_s43_r2\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"D114 Method A: 1.7B RSFT k=1 s43 重跑。使用 s42 SFT adapter (sft_output_qwen3_1_7b_bf16) + s42 CED k=1 scored data, RSFT seed=43。原始运行输出被误删(Worker B 误判)，需重新训练。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s44 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 44。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan019_1_7b_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B RSFT k=1 s43 (Option A seed expansion): 复用 s42 SFT adapter + s42 CED k=1 scored data，只变 RSFT 训练 seed 为 43。验证 1.7B 尺度 RSFT 增益跨 seed 稳健性。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan019_8b_rsft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT s44 eval (Option A seed expansion). 预期 ign_f1 接近 canonical s42 (0.5376)，验证 RSFT 增益在 8B 尺度跨 seed 稳定。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_ced_score\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step 2: CED scoring + k=1 selection on SFT s44 generation candidates. 使用 NLI-DeBERTa 对 N=8 候选打分，format_w=0.2, f1_w=0.4, ced_w=0.4，top_k=1 筛选最优样本用于后续 RSFT 训练。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_train\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"hypothesis\\\": \\\"D112 step 3: RSFT training on SFT s44 base using CED k=1 scored data. 在最强 SFT seed (s44, ign_f1=0.4734) 上验证 RSFT 效果，参数与 canonical s42 RSFT 完全一致。\\\"}, \\\"plan017_14b_sft\\\": {\\\"status\\\": \\\"RUNNING\\\"}, \\\"d111_4b_sft_s42_reeval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-evaluating 4B SFT s42 with D076 standardized protocol to establish fair 3-seed comparison with s43 and s44. Previous s42 evaluations gave inconsistent results (0.4106/0.4036/0.3974), so re-running with identical protocol resolves this.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 3: 并行候选生成 (docs [2268:3027])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 1: 并行候选生成 (docs [756:1512])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 2: 并行候选生成 (docs [1512:2268])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_gen_shard0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 shard 0: 并行候选生成 (docs [0:756])，用 SFT s44 adapter 生成 N=8 RSFT 候选。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d112_rsft_s44_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D112 step1: 用 SFT s44 adapter (ign_f1=0.4734, 最强 seed) 生成 N=8 RSFT 候选。验证 RSFT pipeline 从强 SFT base 出发是否能进一步提升，决定 Claim 1 表述强度。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan019_8b_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B RSFT seed44 (Option A: seed expansion). Reuses s42 SFT adapter + s42 CED k=1 scored data, only changes RSFT training seed to 44. Tests if RSFT gain is robust across seeds at 8B scale. Expected: ign_f1 similar to canonical 8B RSFT s42.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_8b_sft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B SFT s44 eval (D076 protocol): measure SFT baseline for seed44 at 8B scale. Paired with canonical s42 (ign_f1=0.5051) for 2-seed mean±std.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"grpo_bf16_g4_ckpt200_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO bf16 G=4 checkpoint-200 eval (final): compare with ckpt-100 for D106 learning curve. If ckpt-200 > ckpt-100, GRPO is improving. Expected: rel_f1 improvement over ckpt-100.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"random_rsft_k1_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Random k=1 RSFT baseline: same candidate pool as CED RSFT but random selection instead of CED scoring. If random RSFT significantly underperforms CED RSFT (rel_f1 gap > 1.5pp), proves CED scoring precision is the key, not just data filtering quantity. CED k=1 mean rel_f1=0.4596, expect random < 0.445.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 and s43 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s44_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B SFT seed44 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s44_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval 1.7B SFT seed43 on DocRED dev set to measure RE performance. Paired with s42 for 2-seed mean±std at 1.7B scale.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s43_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B SFT seed43 eval r2 (corrected D076 command: --model_path=base --sft_adapter=adapter). Re-run of failed wave1_sft_4b_s43_eval. Expected rel_f1 ~50.5 based on canonical 4B SFT s42.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_8b_sft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"8B Qwen3 SFT seed44: scaling seeds for statistical robustness. Paired with canonical s42 for 2-seed mean±std at 8B scale. Expected train_loss similar to canonical 8B SFT.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed43 r2: third seed for 1.7B scaling robustness. s42 ign_f1=0.4786, s44 ign_f1=0.4321, variance=4.65pp is extreme. Third seed critical to determine if s44 is outlier or s42 is outlier.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_grpo_bf16_g4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO bf16 without quantization (G=4): prior GRPO runs used int4 quantization which may have caused training instability. bf16 full precision should provide clean GRPO signal. If GRPO improves over RSFT, validates Claim 2 (decoupling spectrum). Expected: rel_f1 > RSFT baseline (~52pp).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"random_rsft_k1_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Random k=1 RSFT eval: if random selection significantly underperforms CED RSFT (gap > 1.5pp in rel_f1), proves CED scoring precision is the key differentiator. CED k=1 mean rel_f1=0.4596, expect random &lt; 0.445.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"grpo_bf16_g4_ckpt100_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO bf16 G=4 checkpoint-100 eval (D106 conditional termination): evaluate mid-training checkpoint to decide whether to continue GRPO training to step 200. If rel_f1 >= RSFT baseline (~52pp), continue. If significantly below, consider early termination.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed44 eval (D076 protocol): measure baseline SFT performance for seed44 at 1.7B scale. Paired with canonical s42 for scaling seed robustness. Expected rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan019_1_7b_sft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"1.7B SFT seed43: scaling seeds for statistical robustness. Paired with canonical s42 and s44 for 3-seed mean±std at 1.7B scale. Expected train_loss ~0.70, rel_f1 ~49.5 based on canonical 1.7B SFT.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"wave1_sft_4b_s44_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT 4B seed44 eval (D076 protocol): baseline SFT performance for seed44. Paired with s43 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"wave1_sft_4b_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT 4B seed43 eval (D076 protocol): baseline SFT performance for seed43. Paired with s44 for mean±std. Expected rel_f1 ~50.5 based on prior 4B SFT s42 results.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"seed_llama_rsft_k1_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT baseline for Qwen3-4B seed44: second seed for SFT baseline. Paired with seed43 for mean±std reporting. Expected rel_f1 similar to seed43 (~50.5±1pp).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"wave1_sft_4b_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT baseline for Qwen3-4B seed43: standard SFT without CED filtering. Paired with RSFT to measure CED filtering gain. Expected rel_f1 ~50.5 based on prior 8B SFT results scaled down.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_llama_rsft_k1_s43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-8B RSFT k=1 seed43 eval: paired with s42 (rel_f1=0.5839) for seed robustness. If s43 gives similar results (±1.5pp), cross-architecture RSFT k=1 claim is robust. Expected rel_f1 ~0.58±0.015.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"seed_llama_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_llama_k1_s43_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT k=1 seed43: 与 s42 配对验证种子稳定性。k=1 数据（2952 samples），跨架构验证 CED 筛选在 LLaMA 上的效果。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_8b_rsft_k1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT k=1 seed43，与 s42 配对验证种子稳定性。k=1 数据（3018 samples），超参与 4B canonical 一致。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_8b_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3018 samples vs 9041），预期 rel_f1 与 k=3 相当或略有变化，验证 k=1 在 8B 上同样有效。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_llama_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：LLaMA-8B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（2952 samples vs 8829），跨架构验证 k=1 RSFT 效果。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"d102_1_7b_rsft_k1_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D102 方法论修正：1.7B RSFT 从 k=3 改为 k=1（与论文声明和 4B canonical 一致）。k=1 筛选更严格（3021 samples vs 9042），在最小模型上验证 k=1 RSFT 效果。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"seed_comparison_prep\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan006_1_7b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"rsft_s43_dev_eval_preds\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval RSFT-s43 (CED-scored) on DocRED dev with predictions saved. Prerequisite for Lead 1 CED evidence filtering: per-sentence NLI scoring requires full prediction outputs.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate 1.7B RSFT model (checkpoint-1698) on DocRED dev. Retry after disk-full crash. Validates CED-filtered RSFT at smallest model scale in scaling study.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_r3_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate LLaMA-3.1-8B RSFT r3 (checkpoint-3312, final) on DocRED dev. Cross-architecture validation: if CED-RSFT works on both Qwen and LLaMA, the method is architecture-agnostic.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with CED-scored data (9041 samples) on Qwen3-8B, resume from checkpoint-750 after disk-full crash. At 8B scale, CED-filtered RSFT should achieve highest absolute performance in scaling study.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_seed43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate 1.7B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5219. If seed 43 gives similar result (±1pp, i.e., 0.51-0.53), the 1.7B scaling study datapoint is robust.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_test\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Generate 1.7B RSFT test set predictions for CodaLab submission. 1.7B RSFT dev rel_f1=0.5219, expect similar performance on test.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_test\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Generate 8B RSFT test set predictions for CodaLab submission. 8B RSFT dev rel_f1=0.5606, expect similar performance on test.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_seed43_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev (retry with correct base_model path). Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp), the cross-architecture RSFT claim is robust against seed variance.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_test\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Generate LLaMA-8B RSFT test set predictions for CodaLab submission. LLaMA-8B RSFT dev rel_f1=0.5674, expect similar performance on test.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_seed43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Validate LLaMA-8B RSFT robustness across seeds. Seed 42 gave rel_f1=0.5674 (+1.6pp over SFT baseline 0.5514). If seed 43 gives similar result, the cross-architecture RSFT claim is robust against seed variance.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_llama_rsft_seed43_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate LLaMA-8B RSFT seed 43 on DocRED dev. Seed 42 gave rel_f1=0.5674. If seed 43 gives similar result (±1.5pp, i.e., 0.55-0.58), the cross-architecture RSFT claim is robust against seed variance.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"lead2_ckpt20_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate GRPO checkpoint-20 from RSFT base (lead2_rsft_grpo_ced_r2) on DocRED dev. If RSFT→GRPO preserves/improves rel_f1 over RSFT baseline (0.4601), it validates the RSFT→GRPO training pipeline as viable.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate Qwen3-8B RSFT (CED-scored data, 9041 samples) on DocRED dev. At 8B scale with near-zero evidence tax, CED-RSFT should achieve highest absolute Ign-F1 in the scaling study.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_seed43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with seed 43 on Qwen3-1.7B will produce comparable performance to other seeds, validating seed robustness for the scaling study\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"post_hoc_bm25_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Post-hoc BM25 evidence retrieval on SFT-no-evidence predictions: if retrieving evidence after RE produces comparable joint Evi-F1 and EDCR to jointly trained RSFT, then joint generation is unnecessary. Expect RSFT to have better evidence quality (lower EDCR) due to training-time evidence grounding.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"lead1_ced_evidence_filter\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"hypothesis\\\": \\\"Post-hoc CED-based evidence filtering on RSFT predictions: removing low-NLI-score evidence sentences at inference time should improve Evi-F1 and EDCR by eliminating distractor citations, without affecting rel_f1.\\\"}, \\\"plan_006_qwen3_8b_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with CED-scored data (9041 samples) on Qwen3-8B will improve rel_f1 over SFT baseline. At 8B scale with near-zero evidence tax, CED-filtered RSFT should achieve the highest absolute performance in the model scaling study.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Evaluate 1.7B RSFT model on DocRED dev to measure rel_f1 improvement over SFT baseline. Validates that CED-filtered RSFT generalizes to smallest model scale (1.7B) in the scaling study.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_s44_dev_eval_preds\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-run RSFT s44 dev eval with predictions saved, as prerequisite for CED evidence filtering experiment (线索1: inference-time distractor citation removal). Predictions needed for per-sentence NLI scoring.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"lead2_rsft_grpo_ced_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT→bf16 GRPO two-stage (retry with --data_dir fix): starting from merged RSFT-s43 checkpoint (rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should improve evidence quality (EDCR) while preserving rel_f1.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_train_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"bf16 full-precision training with gradient checkpointing and batch_size=1 will fit within single RTX 5090 32GB VRAM while maintaining training quality comparable to QLoRA, resolving the OOM issues seen in r1/r2 attempts\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"lead2_rsft_grpo_ced\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT→bf16 GRPO two-stage: starting from RSFT best checkpoint (s43, rel_f1=0.46), short-range GRPO (50 steps, lr=1e-6) with CED-only reward should further improve evidence quality (EDCR) while preserving rel_f1, because RSFT provides stable base preventing catastrophic forgetting seen in SFT→GRPO.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_8b_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring on Qwen3-8B RSFT candidates (24216 gens from 3027 docs) will produce high-quality filtered training data. At 8B scale with near-zero evidence tax, CED-filtered RSFT should yield further gains over an already strong SFT baseline.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT with CED-scored data on Qwen3-1.7B will improve relation extraction F1 over SFT baseline by selectively reinforcing high-quality extraction patterns, similar to gains seen on 4B model\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_002_test_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT-CED s44 (best dev config, rel_f1=0.4655) maintains improvement over SFT on held-out test set, confirming CED-filtered rejection sampling gains are not dev-set overfitting. Test Ign-F1 should exceed SFT test baseline.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_8b_rsft_candidates_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Resuming 8B candidate generation from idx 2701 will complete the full RSFT candidate set needed for reward-based filtering and RSFT training\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_016_llama_rsft_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT training retry with OOM fix: --no-quantize (bf16) + gradient_checkpointing. R1 OOM due to missing bf16 flag causing fp32 loading on 32GB card. 8829 CED-filtered samples, 3 epochs.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT training on CED-filtered candidates (8829 samples, top_k=1) should improve rel_f1 over SFT baseline (0.5514), validating that the CED-RSFT pipeline generalizes across model families (Qwen→LLaMA).\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring (NLI-based contrastive discrimination) on LLaMA-3.1-8B RSFT candidates will produce filtered training data that improves RSFT quality, consistent with Qwen3-4B CED results.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_006_qwen3_1_7b_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring (NLI contrastive discrimination) can effectively filter 1.7B model candidates despite lower generation quality: NLI-based selection should identify high-quality evidence samples even from a capacity-limited generator.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_007_redocred_rsft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"hypothesis\\\": \\\"CED-RSFT improvements on DocRED should transfer to Re-DocRED: RSFT model should outperform SFT baseline on Re-DocRED Ign-F1, demonstrating cross-dataset generalization of rejection sampling gains.\\\"}, \\\"plan_006_qwen3_1_7b_rsft_candidates\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B RSFT candidate generation (N=8, T=0.7). Scale ablation: smallest model RSFT candidates for CED scoring. plan_006 claim=3.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_002_test_eval_s44_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"DocRED test set evaluation for RSFT-CED s44 (best dev config). Final benchmark numbers for paper submission; test set performance confirms dev set gains are not overfitting artifacts.\\\"}, \\\"plan_006_qwen3_8b_no_evidence_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-8B no-evidence SFT baseline for evidence tax measurement at 8B scale. If 8B no-evi rel_f1 ≈ 8B evidence-SFT rel_f1, confirms that 8B absorbs evidence cost (tax≈0).\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B no-evidence SFT baseline for evidence tax measurement at 1.7B scale. Paired with evidence-SFT to quantify whether evidence generation constrains or helps small model RE performance.\\\"}, \\\"plan_006_qwen3_1_7b_sft_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: smallest model expected to show highest evidence tax due to capacity-constrained multi-task optimization.\\\"}, \\\"plan_006_qwen3_8b_sft_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-8B bf16 LoRA SFT training for evidence-grounded DocRE. Scale ablation: larger model should achieve higher rel_f1 than 4B (0.4057) and 1.7B baselines, with lower evidence tax due to greater capacity.\\\"}, \\\"reeval_sft_baseline_d076\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Re-eval Qwen3-4B SFT baseline under D076 unified protocol (batch_size=4, no-quantize, max_new_tokens=1024, seed=42). Required as canonical comparison point for all RSFT/GRPO experiments and evidence tax computation.\\\"}, \\\"plan_006_qwen3_1_7b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-1.7B evidence-SFT eval under D076 protocol. Establishes smallest-scale SFT baseline; evidence tax at 1.7B predicted negative (evidence helps small models by constraining over-prediction).\\\"}, \\\"plan_006_qwen3_8b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"Qwen3-8B evidence-SFT eval under D076 unified protocol. Establishes 8B-scale SFT baseline for evidence tax measurement (paired with no-evidence eval) and RSFT improvement quantification.\\\"}, \\\"plan_016_llama_3_1_8b_no_evidence_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B no-evidence SFT baseline for cross-family evidence tax measurement. Paired with evidence-SFT to quantify evidence generation cost on a non-Qwen architecture at 8B scale.\\\"}, \\\"plan_016_llama_3_1_8b_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B can be SFT-trained for evidence-grounded DocRE with the same pipeline as Qwen3 family, enabling cross-family generalization claims for the FREIGE framework.\\\"}, \\\"plan_007_redocred_4b_sft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"FREIGE SFT model trained on DocRED transfers to Re-DocRED without re-training: if Ign-F1 drop <5pp and Evi-F1 maintains, the learned evidence grounding generalizes across annotation schemes.\\\"}, \\\"plan_006_qwen3_8b_no_evidence_eval_v2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"8B model capacity absorbs evidence generation cost: no-evidence SFT and evidence-SFT should produce near-identical rel_f1, demonstrating evidence tax≈0 at 8B scale (contrasting with 4B where tax=-7.5pp).\\\"}, \\\"plan_016_llama_3_1_8b_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B no-evidence SFT should achieve similar rel_f1 to evidence-SFT (tax≈0), cross-family validating the 8B-scale evidence absorption pattern observed in Qwen3-8B.\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval_v3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"1.7B model capacity is insufficient to jointly optimize RE and evidence generation: no-evidence SFT should outperform evidence-SFT on rel_f1, revealing positive evidence tax at small scale (opposite to 8B where tax≈0).\\\"}, \\\"plan_016_llama_3_1_8b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B SFT with evidence generation should achieve comparable rel_f1 to Qwen3-8B SFT, establishing cross-family baseline for evidence tax measurement. Evidence tax at 8B scale predicted near-zero based on Qwen3-8B pattern.\\\"}, \\\"plan_016_llama_grpo_qlora\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"hypothesis\\\": \\\"QLoRA GRPO catastrophic decoupling (format gaming + zero IE ability) is not Qwen-specific: LLaMA-3.1-8B under identical QLoRA GRPO training should exhibit the same failure mode (grad_norm→0, loss→0, rel_f1→0). Cross-family validation of C2.\\\"}, \\\"plan_006_qwen3_8b_rsft_candidates\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Qwen3-8B RSFT candidate generation (N=8, T=0.7). Generates rejection sampling candidates for subsequent CED scoring and filtering. plan_006 claim=3.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_candidates_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT candidate gen r3 (N=8, T=0.7, start_idx=64 resume). Exclusive cuda:2 after GRPO kill.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_007_redocred_rsft_eval_r5\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED-RSFT gains transfer to Re-DocRED (r5, correct 3-param loading: base→SFT→RSFT)\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_007_redocred_rsft_eval_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED-RSFT gains transfer to Re-DocRED (r4, correct 3-param loading: base→SFT→RSFT)\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_002_test_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_007_redocred_rsft_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-DocRED RSFT eval r3 (config fix: model_path=base, sft_adapter=RSFT ckpt). Verify CED-RSFT gains transfer cross-dataset.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_007_redocred_rsft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_014_no_evidence_eval_d076\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"4B no-evidence SFT eval under D076 unified protocol (batch_size=4, max_new_tokens=1024, seed=42, no-quantize). Required for clean scaling comparison across 1.7B/4B/8B.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_016_llama_rsft_candidates_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_016_llama_rsft_candidates\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\", \\\"hypothesis\\\": \\\"LLaMA-3.1-8B RSFT candidate generation (N=8, T=0.7) for cross-family CED-RSFT validation\\\"}, \\\"plan_007_redocred_4b_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval_v2r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval_v2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_1_7b_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_006_qwen3_8b_no_evidence_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"reeval_flat_nli_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval flat-NLI RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 eval_plan_001_flat_nli 用了 batch_size=16。Paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"reeval_ced_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval CED RSFT s44 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + seed=44. 原 eval 用了 batch_size≈16 且 seed=42（错误）。Paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"reeval_ced_s42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 mvp2_eval_rsft_r2b_maxtok1536_r2 用了 batch_size=8 + max_new_tokens=1536。Paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"reeval_flat_nli_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_006_qwen3_1_7b_sft\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"reeval_flat_nli_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval flat-NLI RSFT s43 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + --max_new_tokens 1024. 原 reeval_flat_nli_s43 用了 batch_size=16 导致协议不一致。C3 paired t-test 关键路径。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_rsft_ced_s45\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_rsft_ced_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of CED RSFT seed=43 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 4 个 seed。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_014_no_evidence_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Retry of eval_plan_014_no_evidence with corrected command: --model_path 传底座 Qwen3-4B, --sft_adapter 传 SFT no-evidence adapter。修复 adapter 检测逻辑冲突。plan_id=plan_014, claim=1。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_ced_reranker_poc\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_flat_nli_seed45\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_flat_nli_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"rsft_ced_s45_train_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED RSFT seed=45 训练（r4 重试，r3 因 cuda:2 orphan PID 276148 OOM 失败）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44，s43 在 cuda:1 训练中）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"rsft_ced_s43_train_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_014_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Dev set eval of SFT-no-evidence model (plan_014). 核心目标：对比标准 SFT rel_f1=0.4057 vs 不输出 evidence 的 SFT rel_f1（隔离 evidence generation 代价）。只评估 rel_f1，不评估 evi_f1（输出无 evidence）。plan_id=plan_014, claim=1。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_ced_s45_train_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_ced_s45_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"rsft_ced_s43_train_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED RSFT seed=43 训练（r2 重试，修正 cwd 错误）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"reeval_rsft_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval RSFT top_k=3 WITH --sft_adapter (D064 bug fix). 原 eval_plan_008_rsft_topk3 因缺 --sft_adapter 被 killed。对比 CED RSFT top_k=1 (rel_f1≈0.46) 和 SFT baseline (0.4057)。\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"rsft_ced_s43_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rsft_ced_s45_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"reeval_flat_nli_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-eval flat-NLI RSFT seed=43 WITH --sft_adapter (D064 bug fix). 原 eval_plan_001_flat_nli_s43 因缺 --sft_adapter 导致 rel_f1=0.0022 无效。对比 flat-NLI s42 (rel_f1=0.4539) 和 CED RSFT mean (0.4596)。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_003_edcr_diagnostic\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"EDCR cross-method diagnostic table: 计算所有 evidence-producing 方法（SFT baseline, RSFT-CED best, RSFT-flatNLI best, CED-reranker）的 EDCR，验证 EDCR 作为独立评估指标的诊断能力。plan_id=plan_003, claim=4。GPU 预算 2h。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_flat_nli_seed44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_012_dpo_1ep_fixed_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_001_flat_nli_seed44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_009_dynamics_figure\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO forgetting dynamics 3-panel figure: QLoRA vs BF16 GRPO 的 rel_f1/evi_f1/EDCR 训练轨迹对比。支撑 Claim 3 (task decoupling 是 QLoRA-specific)。plan_id=plan_009。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_001_flat_nli_seed45\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_011_bf16_g8_step_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_011_eval_g8_bf16_ckpt100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_rsft_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT seed=44 checkpoint. First MVP-2 judgement data point. Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798 (SFT baseline).\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_008_topk3_fixed\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_012_dpo_1ep_fixed\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"eval_plan_008_rsft_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\", \\\"hypothesis\\\": \\\"RSFT top_k=3 dev eval: 对比 top_k=1 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1≈0.4057)。验证更多候选是否提升证据质量。\\\"}, \\\"plan_012_dpo_ced\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_012_dpo_ced_1ep\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"DPO+CED 1 epoch retraining: plan_012_dpo_ced 3 epochs 严重过拟合 (rewards_accuracy=1.0, margins 9x膨胀, entropy崩塌)。重训 1 epoch 验证 early stopping 是否消除 overfitting confound。对比 plan_012 3ep + RSFT (rel_f1=0.46) + SFT baseline (rel_f1=0.4057)。\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"eval_plan_001_flat_nli_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"eval_plan_012_dpo_ced_1ep\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_008_rsft_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT top_k=3 训练：用 CED-filtered 的 top-3 候选进行 rejection sampling fine-tuning，验证更多候选是否比 top_k=1 (rel_f1≈0.46) 带来更好的证据质量。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_001_flat_nli_seed43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_009_flatnli_reward_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_009_extract_reward_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"eval_sft_baseline_noquant\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_009_flatnli_reward_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"eval_plan_012_dpo_ced_ckpt400\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_009_forgetting_figure\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_014_sft_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_014_sft_no_evidence\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT-without-evidence ablation: 训练只输出 relation triples（不含 evidence sentences）的 SFT 模型。量化 joint evidence generation 对 extraction 的代价（当前 rel_f1=0.4057 vs 只抽关系的 LMRC 60.7 的 gap 有多少来自 evidence 负担）。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_002_test_eval_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"plan_001_rsft_flat_nli\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"flat-NLI RSFT ablation: 用 flat-NLI scoring（p_pos 概率，无 contrastive margin）筛选的 2691 样本做 RSFT。对比 CED scoring RSFT（2718 样本）。验证 CED 的对比性 margin 是否是关键因素。如 flat-NLI RSFT ≈ CED RSFT → CED 无增益；如 CED RSFT 显著优于 → contrastive margin 关键。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_plan_001_flat_nli\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Dev eval of flat-NLI RSFT (plan_001). 对比 CED RSFT (3-seed mean rel_f1=0.4596). flat-NLI ≈ CED → CED contrastive margin 无增益; CED >> flat-NLI → margin 关键。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"eval_grpo_g8_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval GRPO G=8 bf16 checkpoints 80/90/100 on full dev set (985 docs). 验证 catastrophic forgetting 是否在 bf16 LoRA 下复现。rel_f1>0.30 → forgetting 不复现 (QLoRA-specific); rel_f1<0.05 → 复现 (C2 加强)。对比: SFT rel_f1=0.4057, QLoRA GRPO rel_f1=0.2167 (catastrophic).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_015_grpo_g4_bf16_v3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P2 robustness check: bf16 LoRA GRPO G=4, kl=0.01, lr=5e-6。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean single-variable quantization ablation (Δ=+23.8pp)。v3 仅为 robustness data point，lr=5e-6 与对照组 lr=5e-5 不一致。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_015_grpo_g4_bf16_v2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Robustness check: bf16 LoRA GRPO 在 G=4, kl=0, lr=5e-6 条件下是否也防止 catastrophic forgetting。非 single-variable ablation（kl/lr/G 均与 QLoRA 对照组不同）。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean quantization ablation。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_015_grpo_g4_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"bf16 LoRA GRPO clean control: 与原始 QLoRA GRPO 仅改 quantization（4-bit → bf16），保持 G=4, kl=0, CED reward 不变。验证 catastrophic forgetting 是否由 QLoRA quantization 导致。\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"plan_011_grpo_g8_bf16\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"GRPO G=8 bf16 LoRA: 验证 catastrophic forgetting 是否在 bf16（非 QLoRA 4-bit）下仍复现。CED reward + kl_coef=0.01, 100 steps。如仍 fail → 加强 Claim 3\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_011_grpo_g8_bf16_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"plan_004_dreeam_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Phase A: 复现 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1≈54.15, RE-F1≈63.49。论文报告的57.34是student model在test set的结果，需4阶段self-training pipeline。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2b_maxtok1536_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). Retry with correct model stack (Base+SFT+RSFT). If EDCR improves significantly (from 0.6609 toward 0.71+), truncation is the cause. If unchanged, distractor citation is genuine RSFT behavior.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"plan_001_flat_nli_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"flat-NLI scoring 前置步骤：用 flat_nli 模式（p_pos 概率，无 contrastive margin）对 RSFT 生成候选打分并筛选训练数据。\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_s43_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798. Retry of mvp2_eval_rsft_s43 (fixed arg names).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_ced_scoring_topk3_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Retry with HF_HUB_OFFLINE=1 (NLI model cached locally).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_train_r1_s44\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT training seed=44 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2b\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of r2b (1 epoch, alpha=32, lr=1e-5, clean data). Ablation: conservative LoRA scaling vs r2a/r1. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2a\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of r2a (1 epoch, alpha=128, clean data). Ablation: 1 epoch vs 3 epoch (r1). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT r1 (seed=42). Same pipeline as s44 eval (985 docs, no-quantize). Need 3-seed data for complete_mvp. s44 PASS: rel_f1=0.4655, evi_f1=0.8087.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_sft_baseline\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"SFT baseline eval using identical eval protocol as GRPO evals (eval_lr5e6_ckpt20.sh). Required for MVP-2 core comparison: CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp. Prior SFT eval (r3) used different eval path; this ensures apple-to-apple comparison.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_r2b_maxtok1536\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). If EDCR improves significantly (from 0.6609 toward 0.71+), current EDCR gap is truncation artifact, not model issue. If EDCR unchanged, distractor citation is genuine RSFT behavior.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_ced_scoring_topk3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Answers: does CED filtering strictness affect RSFT training quality?\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_r2b\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT r2b: data fix + training dynamics fix (1 epoch + filter truncated + LoRA alpha=32/r=64 scaling 0.5 + lr=1e-5). Isolates: is conservative LoRA scaling the key factor? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_r2a\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT r2a: data fix only (1 epoch + filter 170 truncated JSON → 2548 samples). Same LoRA alpha=128/r=64, lr=2e-5 as r1. Isolates: does 1 epoch + clean data alone fix the ontology collapse? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_diagnosis\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT failure root cause: rel_f1=0.0483 vs SFT 0.4057. Diagnose: training data distribution (relation count), step-170 checkpoint output analysis, SFT vs RSFT data comparison.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_ced_kl001_r4_last\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_kl001_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr + bash -c wrapping)\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_kl001_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr → --learning_rate)\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_train_r2_fix\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT r2 fix: 4 fixes based on r1 diagnosis. 1) 1 epoch (vs 3), 2) LoRA alpha=32/r=64 (scaling 0.5 vs 2.0), 3) filtered truncated JSON (~2548 vs 2718 samples), 4) lr=1e-5 (vs 2e-5). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_rsft_train_r1_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT training seed=43 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_rsft_s43\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_rsft_train_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT training on CED-filtered data (2718 samples, mean CED=0.668). SFT warmup baseline: rel_f1=0.4057, evi_f1=0.798. Pass criteria: rel_f1 > 0.4057 AND evi_f1 > 0.798.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_ced_scoring\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED scoring + filtering on 4 shard RSFT generations. top_k=1, f1_threshold=0.1. 21952 → 2718 selected (12.4%).\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s0\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 0/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 3/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 2/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_gen_s1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation shard 1/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_rsft_generate\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT generation phase: SFT model generates N=8 candidate outputs per training sample at T=0.7. CED scoring + filtering后作为 RSFT 训练数据。D031 pivot 方向。\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_diversity_probe\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"RSFT viability check: SFT model output diversity at T=0.7/1.0 with N=8 generations. Pass criteria: unique triple-sets >= 5/8.\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-100 eval: lr=5e-6 GRPO at step 100 (halfway point). Checkpoint-100 已保存。与 kl001_r4 的 step-100 (rel_f1=0.217) 形成直接对比。Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_ced_lr5e6_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D030/P0: lr=5e-6 (10x lower than ced_kl001_r4) prevents catastrophic forgetting while maintaining CED reward improvement. Community consensus GRPO+QLoRA lr=5e-6~1e-5. Pass criteria: ckpt-20 rel_f1 > 0.30. Extra monitoring: pred_count + recall trend.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt80\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-80 eval: lr=5e-6 GRPO at step 80. 训练轨迹继续——ckpt-20 FAIL (0.0077), ckpt-40/60 待出. Step 80 reward=0.283 (回升), format_reward=0.249. Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt60_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-60 eval retry: 原 submit_on_allocated 失败 (pid=unknown). 手动 SSH 启动 /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh. Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt60\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-60 eval: lr=5e-6 GRPO at step 60. 训练轨迹数据点——ckpt-20 catastrophic forgetting (rel_f1=0.0077)，需看后续 checkpoint 是否恢复。Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt40_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-tracking orphan PID 101842 for P0 ckpt-40 eval (lr=5e-6 GRPO step 40). Original exp auto-failed due to cron/PID mismatch. Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt20\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-20 early eval: lr=5e-6 GRPO at step 20. Pass criteria: rel_f1 > 0.30 (no catastrophic forgetting). Key MVP gate for P0.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_lr5e6_rp_r2_ckpt20\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0+P1 ckpt-20 eval: lr=5e-6 + recall_penalty GRPO at step 20. Director killed rp_r2 training (loss divergence), but ckpt-20 eval needed to close P0+P1 comparison line. Pass criteria: rel_f1 > 0.30 AND pred_count >= 9720.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_lr5e6_r1_ckpt40\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"P0 ckpt-40 eval: lr=5e-6 GRPO at step 40 (where f1_reward first rises to 0.038). Director 新判定框架: ckpt-20 FAIL + ckpt-40 PASS → P0 判 PASS。Pass criteria: rel_f1 > 0.30.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_lr5e6_rp_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D032/P0+P1 retry: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 (lr5e6_r1) isolates CED shortcut fix contribution. Retry of rp_r1 which failed due to bash quoting.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_ced_kl001_r4_multi\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_lr5e6_rp_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D032/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_lr5e6_p1_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"D031/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 15000 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_ced_kl001_r4_step90\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval true best checkpoint (step 90, reward=1.370). Critical after ckpt-50 showed reward hacking (rel_f1 -24.9pp). If step 90 also fails, CED reward design has fundamental issue.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_ced_kl001_r4_ckpt7080\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Re-run failed ckpt-70/80 eval from crashed high eval (cuda:3 OOM). Completes 10-checkpoint trajectory for paper negative result analysis.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_eval_ced_kl001_r4_high\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"High-end checkpoint eval (60,70,80,90) on cuda:3, complementing cuda:2 low-end eval. Step 90 is true best checkpoint (reward=1.370). D024 directive.\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_eval_ced_kl001_r4_step100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval ced_kl001_r4 last checkpoint (step 100) to compare with best-reward checkpoint (step 50). If best ≠ last, the gap measures training stability under batch_size=1 GRPO variance.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_eval_ced_kl001_r4_ckpt90\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Eval ced_kl001_r4 best-reward checkpoint (step 90, reward=1.370, f1=0.720) — this is the primary MVP-2 judgment checkpoint. If evi_f1 ≥ SFT baseline (0.7979) + 2pp = 0.8179, MVP-2 passes.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_eval_ced_kl001_r4_ckpt10\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_eval_ced_kl001_r4_early\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_flatnli_r6\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Flat-NLI reward with kl_coef=0.01 + num_generations=8 from SFT scratch (not resume). 100-step probe to verify stability. Same D020 config as ced_kl001_r4 (which is healthy). Tests whether flat-NLI reward type works under stable training config.\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_ced_kl001_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_grpo_extract_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0.01 + num_generations=8 trains stably. 100-step probe parallel ablation with ced_kl001_r4 (CED reward) to compare reward type impact under identical stability config.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_flatnli_r5\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Flat-NLI reward with kl_coef=0.01 + num_generations=8 prevents mode collapse. Resume from flatnli_r3 checkpoint-100 (healthy). 100-step probe (steps 100→200) to verify stability before full run.\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_sft_eval_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_grpo_extract_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_flatnli_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_kl001\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_r5\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\"}, \\\"mvp2_grpo_flatnli_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_sft_eval_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_sft_eval\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_flatnli_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_extract_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_r4\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_extract\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Extraction-only reward (format+F1, no CED) establishes GRPO baseline — CED r3 should exceed this on Evi-F1\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_flatnli\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"Flat-NLI reward (non-contrastive) improves Evi-F1 over extraction-only but less than CED — validates contrastive component's incremental value\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"hypothesis\\\": \\\"CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + stable training (num_iterations=1, KL early stop at 100) + kl_coef=0.05 improves Evi-F1 over SFT baseline\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"mvp2_grpo_ced_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced_r1\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"mvp2_grpo_ced\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"precompute_nli_train\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp2_sft_warmup\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"smoke_test_grpo\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"mvp1_ced_signal\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}}, \\\"count\\\": 237, \\\"total\\\": 237, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.7213}}\"}",
      "numLines": 1,
      "startLine": 1,
      "totalLines": 1
    }
  }
}
```

</details>

---

### Assistant

_source line 18_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the experiment_plan.yaml file directly from disk.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "aa44e1a0-7ffb-445a-b1e4-a33d6bda6a7f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DLnisUzvtdCRqVTwJgBMoA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22476,
      "cache_read_input_tokens": 27830,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 22476
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_012FQAUJFMk72EfpVC68gugu`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "ef9647c3-5695-4c3a-aef5-7b485f45ff95",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DLnisUzvtdCRqVTwJgBMoA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22476,
      "cache_read_input_tokens": 27830,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 22476
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-19T05:44:25.681Z_

<details><summary>↩ Tool result · `toolu_012FQAUJFMk72EfpVC68gugu`</summary>

```text
1	experiments:
2	- id: plan_001
3	  claim: 2
4	  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选
5	    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py
6	    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'
7	  priority: P0
8	  gpu_budget_hours: 20
9	  deps: []
10	  registry_id: eval_flat_nli_seed45
11	- id: plan_002
12	  claim: 1
13	  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set
14	    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'
15	  priority: P0
16	  gpu_budget_hours: 4
17	  deps:
18	  - plan_001
19	  registry_id: plan_002_test_rsft_s44
20	- id: plan_003
21	  claim: 4
22	  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing
23	    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'
24	  priority: P0
25	  gpu_budget_hours: 2
26	  deps:
27	  - plan_001
28	  registry_id: plan_003_edcr_diagnostic
29	- id: plan_004
30	  claim: 1
31	  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)
32	    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'
33	  priority: P0
34	  gpu_budget_hours: 8
35	  deps: []
36	  registry_id: plan_004_dreeam_baseline
37	- id: plan_005
38	  claim: 1
39	  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'
40	  priority: P1
41	  gpu_budget_hours: 6
42	  deps: []
43	  registry_id: mvp2_ced_reranker_poc
44	- id: plan_006
45	  claim: 1
46	  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT
47	    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope
48	    不足问题。'
49	  priority: P0
50	  gpu_budget_hours: 32
51	  deps: []
52	  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3
53	- id: plan_007
54	  claim: 1
55	  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config
56	    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%
57	    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的
58	    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'
59	  priority: P0
60	  gpu_budget_hours: 16
61	  deps: []
62	  registry_id: plan_007_redocred_rsft_eval_r5
63	- id: plan_016
64	  claim: 2
65	  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心
66	    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO
67	    QLoRA 是否也出现 catastrophic forgetting。'
68	  priority: P0
69	  gpu_budget_hours: 40
70	  deps: []
71	  registry_id: plan_016_llama_rsft_candidates
72	- id: plan_008
73	  claim: 2
74	  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格
75	    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'
76	  priority: P1
77	  gpu_budget_hours: 8
78	  deps: []
79	  registry_id: reeval_rsft_topk3
80	- id: plan_011
81	  claim: 3
82	  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward
83	    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要
84	    gradient_accumulation 适配显存。'
85	  priority: P0
86	  gpu_budget_hours: 8
87	  deps: []
88	  registry_id: plan_011_bf16_g8_step_eval
89	- id: plan_012
90	  claim: 3
91	  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred
92	    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求
93	    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'
94	  priority: P0
95	  gpu_budget_hours: 12
96	  deps: []
97	  registry_id: plan_012_dpo_ced
98	- id: plan_013
99	  claim: 4
100	  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations
101	    说明替代。'
102	  priority: CANCELLED
103	  gpu_budget_hours: 0
104	  deps: []
105	  registry_id: null
106	- id: plan_009
107	  claim: 3
108	  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward
109	    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心
110	    figure。数据已有，只需汇总+画图。'
111	  priority: P0
112	  gpu_budget_hours: 2
113	  deps: []
114	  registry_id: plan_009_dynamics_figure
115	- id: plan_010
116	  claim: 1
117	  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer
118	    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'
119	  priority: P1
120	  gpu_budget_hours: 4
121	  deps: []
122	  registry_id: null
123	- id: plan_014
124	  claim: 1
125	  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含
126	    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream
127	    v2 三档一致要求。用于回答"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担"。'
128	  priority: P0
129	  gpu_budget_hours: 8
130	  deps: []
131	  registry_id: plan_014_sft_no_evidence
132	- id: plan_015
133	  claim: 2
134	  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED
135	    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:
136	    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream
137	    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于
138	    plan_011 eval 结果。'
139	  priority: P0
140	  gpu_budget_hours: 8
141	  deps:
142	  - plan_011
143	  registry_id: wave1_grpo_bf16_g4
144	- id: plan_mvp1
145	  claim: 1
146	  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing
147	    distractor 的能力验证'
148	  priority: P0
149	  gpu_budget_hours: 1
150	  deps: []
151	  registry_id: mvp1_ced_signal
152	- id: plan_mvp2_sft
153	  claim: 1
154	  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'
155	  priority: P0
156	  gpu_budget_hours: 4
157	  deps: []
158	  registry_id: mvp2_sft_warmup
159	- id: plan_mvp2_rsft
160	  claim: 1
161	  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部
162	    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,
163	    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'
164	  priority: P0
165	  gpu_budget_hours: 20
166	  deps:
167	  - plan_mvp1
168	  - plan_mvp2_sft
169	  registry_id: mvp2_rsft_train_r1
170	- id: plan_mvp2_grpo
171	  claim: 3
172	  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1
173	    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic
174	    forgetting。D031/D033 完整轨迹支撑 Claim 3'
175	  priority: P0
176	  gpu_budget_hours: 60
177	  deps:
178	  - plan_mvp2_sft
179	  registry_id: mvp2_grpo_ced_lr5e6_r1
180	- id: plan_017
181	  claim: 3
182	  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT
183	    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090
184	    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'
185	  priority: P0
186	  gpu_budget_hours: 50
187	  deps: []
188	  registry_id: null
189	- id: plan_018
190	  claim: 1
191	  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)
192	    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt
193	    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 "only Wikipedia domain"
194	    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'
195	  priority: P2
196	  gpu_budget_hours: 60
197	  deps: []
198	  registry_id: null
199	- id: plan_019
200	  claim: 3
201	  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补
202	    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个
203	    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean
204	    ± std，scaling claim 有统计力。'
205	  priority: P0
206	  gpu_budget_hours: 25
207	  deps: []
208	  registry_id: plan019_1_7b_sft_s43_r2
209	  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,
210	    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,
211	    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA
212	    s43/s44。'
213	- id: plan_020
214	  claim: 3
215	  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)
216	    output length distribution with vs without evidence (2) truncation rate 差异（1.7B
217	    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without
218	    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析
219	    + 少量补充 eval。'
220	  priority: P1
221	  gpu_budget_hours: 10
222	  deps: []
223	  registry_id: null
224	- id: plan_021
225	  claim: 1
226	  description: 'Deep error analysis: 按 relation type / document length / entity count
227	    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings
228	    的 insight 层——Main 论文解释 why，Findings 只报 what。'
229	  priority: P1
230	  gpu_budget_hours: 5
231	  deps: []
232	  registry_id: null
233	- id: plan_022
234	  claim: 3
235	  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT
236	    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'
237	  priority: P2
238	  gpu_budget_hours: 30
239	  deps: []
240	  registry_id: null
241	- id: plan_023
242	  claim: 1
243	  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative
244	    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'
245	  priority: P2
246	  gpu_budget_hours: 10
247	  deps: []
248	  registry_id: null
249	- id: plan_w3_sft_seeds
250	  claim: 1
251	  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)
252	    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。
253	  priority: P0
254	  gpu_budget_hours: 8
255	  deps: []
256	  registry_id: wave1_sft_4b_s44_eval_r2
257	- id: plan_d112
258	  claim: 1
259	  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).
260	    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:
261	    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'
262	  priority: P0
263	  gpu_budget_hours: 8
264	  deps:
265	  - plan_w3_sft_seeds
266	  registry_id: d112_rsft_s44_gen_shard0
267	- id: plan_w18_random
268	  claim: 1
269	  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based
270	    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT
271	    有效的关键。Wave 1 实验。
272	  priority: P0
273	  gpu_budget_hours: 4
274	  deps: []
275	  registry_id: random_rsft_k1_eval
276	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "cdb80a65-d98d-4969-a9cf-7784b9e497d9",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
      "content": "experiments:\n- id: plan_001\n  claim: 2\n  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选\n    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py\n    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'\n  priority: P0\n  gpu_budget_hours: 20\n  deps: []\n  registry_id: eval_flat_nli_seed45\n- id: plan_002\n  claim: 1\n  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set\n    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'\n  priority: P0\n  gpu_budget_hours: 4\n  deps:\n  - plan_001\n  registry_id: plan_002_test_rsft_s44\n- id: plan_003\n  claim: 4\n  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing\n    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_001\n  registry_id: plan_003_edcr_diagnostic\n- id: plan_004\n  claim: 1\n  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)\n    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_004_dreeam_baseline\n- id: plan_005\n  claim: 1\n  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'\n  priority: P1\n  gpu_budget_hours: 6\n  deps: []\n  registry_id: mvp2_ced_reranker_poc\n- id: plan_006\n  claim: 1\n  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT\n    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope\n    不足问题。'\n  priority: P0\n  gpu_budget_hours: 32\n  deps: []\n  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3\n- id: plan_007\n  claim: 1\n  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config\n    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%\n    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的\n    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'\n  priority: P0\n  gpu_budget_hours: 16\n  deps: []\n  registry_id: plan_007_redocred_rsft_eval_r5\n- id: plan_016\n  claim: 2\n  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心\n    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO\n    QLoRA 是否也出现 catastrophic forgetting。'\n  priority: P0\n  gpu_budget_hours: 40\n  deps: []\n  registry_id: plan_016_llama_rsft_candidates\n- id: plan_008\n  claim: 2\n  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格\n    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'\n  priority: P1\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: reeval_rsft_topk3\n- id: plan_011\n  claim: 3\n  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward\n    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要\n    gradient_accumulation 适配显存。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_011_bf16_g8_step_eval\n- id: plan_012\n  claim: 3\n  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred\n    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求\n    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'\n  priority: P0\n  gpu_budget_hours: 12\n  deps: []\n  registry_id: plan_012_dpo_ced\n- id: plan_013\n  claim: 4\n  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations\n    说明替代。'\n  priority: CANCELLED\n  gpu_budget_hours: 0\n  deps: []\n  registry_id: null\n- id: plan_009\n  claim: 3\n  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward\n    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心\n    figure。数据已有，只需汇总+画图。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: plan_009_dynamics_figure\n- id: plan_010\n  claim: 1\n  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer\n    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'\n  priority: P1\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: null\n- id: plan_014\n  claim: 1\n  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含\n    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream\n    v2 三档一致要求。用于回答\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\"。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_014_sft_no_evidence\n- id: plan_015\n  claim: 2\n  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED\n    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:\n    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream\n    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于\n    plan_011 eval 结果。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_011\n  registry_id: wave1_grpo_bf16_g4\n- id: plan_mvp1\n  claim: 1\n  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing\n    distractor 的能力验证'\n  priority: P0\n  gpu_budget_hours: 1\n  deps: []\n  registry_id: mvp1_ced_signal\n- id: plan_mvp2_sft\n  claim: 1\n  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: mvp2_sft_warmup\n- id: plan_mvp2_rsft\n  claim: 1\n  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部\n    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,\n    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'\n  priority: P0\n  gpu_budget_hours: 20\n  deps:\n  - plan_mvp1\n  - plan_mvp2_sft\n  registry_id: mvp2_rsft_train_r1\n- id: plan_mvp2_grpo\n  claim: 3\n  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1\n    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic\n    forgetting。D031/D033 完整轨迹支撑 Claim 3'\n  priority: P0\n  gpu_budget_hours: 60\n  deps:\n  - plan_mvp2_sft\n  registry_id: mvp2_grpo_ced_lr5e6_r1\n- id: plan_017\n  claim: 3\n  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT\n    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090\n    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'\n  priority: P0\n  gpu_budget_hours: 50\n  deps: []\n  registry_id: null\n- id: plan_018\n  claim: 1\n  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)\n    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt\n    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 \"only Wikipedia domain\"\n    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'\n  priority: P2\n  gpu_budget_hours: 60\n  deps: []\n  registry_id: null\n- id: plan_019\n  claim: 3\n  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补\n    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个\n    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean\n    ± std，scaling claim 有统计力。'\n  priority: P0\n  gpu_budget_hours: 25\n  deps: []\n  registry_id: plan019_1_7b_sft_s43_r2\n  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,\n    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,\n    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA\n    s43/s44。'\n- id: plan_020\n  claim: 3\n  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)\n    output length distribution with vs without evidence (2) truncation rate 差异（1.7B\n    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without\n    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析\n    + 少量补充 eval。'\n  priority: P1\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_021\n  claim: 1\n  description: 'Deep error analysis: 按 relation type / document length / entity count\n    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings\n    的 insight 层——Main 论文解释 why，Findings 只报 what。'\n  priority: P1\n  gpu_budget_hours: 5\n  deps: []\n  registry_id: null\n- id: plan_022\n  claim: 3\n  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT\n    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'\n  priority: P2\n  gpu_budget_hours: 30\n  deps: []\n  registry_id: null\n- id: plan_023\n  claim: 1\n  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative\n    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'\n  priority: P2\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_w3_sft_seeds\n  claim: 1\n  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)\n    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: wave1_sft_4b_s44_eval_r2\n- id: plan_d112\n  claim: 1\n  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).\n    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:\n    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_w3_sft_seeds\n  registry_id: d112_rsft_s44_gen_shard0\n- id: plan_w18_random\n  claim: 1\n  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based\n    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT\n    有效的关键。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: random_rsft_k1_eval\n",
      "numLines": 276,
      "startLine": 1,
      "totalLines": 276
    }
  }
}
```

</details>

---

### Assistant

_source line 21_

<details><summary>Logged reasoning block</summary>

```text
Now I need to cross-reference each experiment_plan entry's `registry_id` with the actual registry experiments. Let me organize the data.

Registry experiments (exp_id → status):
I have 237 experiments total. Let me extract the key ones.

Let me go through each plan entry and check:

1. **plan_001** (CED vs flat-NLI RSFT ablation)
   - Current registry_id: `eval_flat_nli_seed45`
   - Registry: `eval_flat_nli_seed45` → DONE, success
   - This seems correct — it's the final eval for the flat-NLI ablation
   
2. **plan_002** (Test set evaluation)
   - Current registry_id: `plan_002_test_rsft_s44`
   - Registry: `plan_002_test_rsft_s44` → DONE, success
   - Correct

3. **plan_003** (EDCR pipeline)
   - Current registry_id: `plan_003_edcr_diagnostic`
   - Registry: `plan_003_edcr_diagnostic` → DONE, success
   - Correct

4. **plan_004** (DREEAM baseline)
   - Current registry_id: `plan_004_dreeam_baseline`
   - Registry: `plan_004_dreeam_baseline` → DONE, success
   - Correct

5. **plan_005** (CED-

as-reranker)
   - Current registry_id: `mvp2_ced_reranker_poc`
   - Registry: `mvp2_ced_reranker_poc` → DONE, success
   - Correct

6. **plan_006** (Model size ablation)
   - Current registry_id: `plan_006_qwen3_1_7b_no_evidence_eval_v3`
   - Registry: `plan_006_qwen3_1_7b_no_evidence_eval_v3` → DONE, success
   - This is a multi-step plan with multiple experiments, but the registry_id only captures one of them. The description mentions running the full SFT → RSFT → eval pipeline across both Qwen3-1.7B and Qwen3-8B models, so there should be additional registry entries for the other experiments.

7. **plan_007** (Re-DocRED cross-dataset)
   - Current registry_id: `plan_007_redocred_rsft_eval_r5`
   - Registry: `plan_007_redocred_rsft_eval_r5` → DONE, success
   - Correct

8. **plan_016** (LLaMA cross-family)
   - Current registry_id: `plan_016_llama_rsft_candidates`
   - Registry: `plan_016_llama_rsft_candidates` → DONE, failed
   - Need to investigate why this one failed when there are more recent successful runs like `plan_016_llama_rsft_candidates_r3`, the training variant `plan_016_llama_rsft_train_r3`, and the GRPO experiment `plan_016_llama_grpo_qlora`. Since the plan is focused on validating the decoupling spectrum across model families, the GRPO result seems most relevant, but I should determine which represents the final or most important outcome.

For plan_008, the top_k ablation with `reeval_rsft_topk3` showing negative results is correctly registered. Plan_011's GRPO G=8 evaluation also appears properly linked to its registry entry.

Moving through the remaining experiments: plan_012's DPO+CED approach came back negative as expected, plan_013 was cancelled so no registry needed, and plan_009's dynamics figure successfully completed. Plan_010 for NLI ablation hasn't been started yet with no registry entry, which is fine. Now checking plan_014 for the SFT-without-evidence setup... Continuing through the plan registry checks—plan_mvp2_sft completed successfully with the warmup configuration, plan_mvp2_rsft also finished as expected, and for plan_mvp2_grpo I'm seeing that while the primary registry entry was killed, there's a more successful variant with the KL penalty adjustment that should probably be marked as the canonical result instead. I need to update the GRPO experiment reference from the killed run to the completed one that shows the failure, since `mvp2_grpo_ced_kl001_r4` finished successfully and demonstrates the catastrophic failure supporting the claim. Then I'm going through the remaining experiments: plan_017 needs its registry_id updated to `plan017_14b_sft` which is currently running, plan_018 hasn't started yet so null is correct, and I'm checking plan_019's status.

For plan_019, the registry shows `plan019_1_7b_sft_s43_r2` as completed successfully, but there are also running variants with RSFT that seem contradictory—one shows RUNNING status but has a success conclusion, which suggests the registry might have been updated with results before the status field was changed. The notes indicate the 8B-Qwen RSFT with 2 seeds is done, with some remaining work to complete. Looking back at the registry more carefully, I see the actual experiment IDs don't match what I initially noted—the ones that are actually running are the RSFT variants with s44 and s43, while the plain SFT experiment I mentioned doesn't appear to exist in the registry. Let me verify which of these running experiments should be the representative ID for this plan group. The currently running RSFT experiments are more recent than what the registry is pointing to, so I should consider whether it makes sense to reference an in-progress experiment instead of a completed one for a multi-step plan that's still evolving.

Now I'm thinking through what "in sync" actually means here. The user wants registry_ids to match reality: fix broken references, fill in missing ones, and when there are multiple runs of the same experiment, point to the latest version. For plan_016, I need to decide which experiment best represents the plan's core claim—whether that's the most recent successful RSFT run or the GRPO experiment that directly addresses the catastrophic forgetting concern.

I'm settling on the GRPO experiment as the most representative since that's the central claim, so I'll update plan_016 to point to `plan_016_llama_grpo_qlora`. For plan_mvp2_grpo, the original reference was killed, so I'm replacing it with the successful QLoRA GRPO run that actually documented the catastrophic forgetting behavior. Plan_017 is straightforward—it's currently running, so I'll fill in the null with `plan017_14b_sft`. For plan_019, the SFT step is complete and successful, but I need to check what the most representative current experiment is since there are newer RSFT runs in progress. Looking at plan_d112, it's a multi-step pipeline where the generation phase is complete across all shards, and now I need to figure out which step to point to—whether it's the finished generation shards or if there are downstream steps like CED scoring or RSFT training that are currently active. Looking at the other plan_006 experiments, I can see several completed RSFT and eval runs across different model sizes—the 8B Qwen3 variants finished successfully, though there's some overlap with plan_016 territory that I need to sort out.

Since the description specifically calls for validating evidence tax and RSFT gains across model scales, the no-evidence eval is actually the right choice here, so I'll stick with the current registry_id.

Now checking plan_w3_sft_seeds, which has `wave1_sft_4b_s44_eval_r2` marked as done, though there was an earlier failed attempt.

Looking at the r2 versions that succeeded, the current pointer to the latest successful run is correct. Same with plan_w18_random—`random_rsft_k1_eval` is already pointing to the right completed run.

So I need to update three registry entries: plan_016 should point to the llama grpo qlora variant instead, plan_mvp2_grpo needs to shift to the kl001 r4 version, and plan_017 has another change pending.

Now I'm cross-checking each of these experiment IDs against the registry to confirm they exist and completed successfully. Continuing through the rest of the experiment entries to verify they all point to valid exp_ids...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "9bc4363c-17ec-42bf-b8ea-b6ec647fed3d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YYmK4cqn7y7pUvoaThiy2G",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5822,
      "cache_read_input_tokens": 50306,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5822
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 22_

数据已加载。对照 registry，发现 5 处需要更新的 registry_id：

| plan_id | 旧 registry_id | 问题 | 新 registry_id |
|---------|----------------|------|----------------|
| plan_016 | `plan_016_llama_rsft_candidates` | failed，有成功重跑 r3 + GRPO 实验 | `plan_016_llama_grpo_qlora` |
| plan_mvp2_grpo | `mvp2_grpo_ced_lr5e6_r1` | killed，不是完整实验 | `mvp2_grpo_ced_kl001_r4` |
| plan_017 | `null` | 实验已存在 (RUNNING) | `plan017_14b_sft` |
| plan_019 | `plan019_1_7b_sft_s43_r2` | SFT 步骤已完成，RSFT 步骤在跑 | `plan019_1_7b_rsft_s44_r2` |
| plan_d112 | `d112_rsft_s44_gen_shard0` | gen 步骤已完成，train 步骤在跑 | `d112_rsft_s44_train` |

执行更新：

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "4aa10868-4d7d-4f8a-9b0a-f667170cb9cc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YYmK4cqn7y7pUvoaThiy2G",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5822,
      "cache_read_input_tokens": 50306,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5822
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Edit · `toolu_01F8s2c6RjBpjaFAnzAEDPKD`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
  "old_string": "  registry_id: plan_016_llama_rsft_candidates",
  "new_string": "  registry_id: plan_016_llama_grpo_qlora"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "8181d180-c94a-4691-9b07-bb33f59894ad",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YYmK4cqn7y7pUvoaThiy2G",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5822,
      "cache_read_input_tokens": 50306,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5822
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-19T05:46:11.734Z_

<details><summary>↩ Tool result · `toolu_01F8s2c6RjBpjaFAnzAEDPKD`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "7f79e537-fedd-439f-8822-49abc4f24379",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
    "oldString": "  registry_id: plan_016_llama_rsft_candidates",
    "newString": "  registry_id: plan_016_llama_grpo_qlora",
    "originalFile": "experiments:\n- id: plan_001\n  claim: 2\n  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选\n    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py\n    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'\n  priority: P0\n  gpu_budget_hours: 20\n  deps: []\n  registry_id: eval_flat_nli_seed45\n- id: plan_002\n  claim: 1\n  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set\n    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'\n  priority: P0\n  gpu_budget_hours: 4\n  deps:\n  - plan_001\n  registry_id: plan_002_test_rsft_s44\n- id: plan_003\n  claim: 4\n  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing\n    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_001\n  registry_id: plan_003_edcr_diagnostic\n- id: plan_004\n  claim: 1\n  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)\n    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_004_dreeam_baseline\n- id: plan_005\n  claim: 1\n  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'\n  priority: P1\n  gpu_budget_hours: 6\n  deps: []\n  registry_id: mvp2_ced_reranker_poc\n- id: plan_006\n  claim: 1\n  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT\n    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope\n    不足问题。'\n  priority: P0\n  gpu_budget_hours: 32\n  deps: []\n  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3\n- id: plan_007\n  claim: 1\n  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config\n    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%\n    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的\n    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'\n  priority: P0\n  gpu_budget_hours: 16\n  deps: []\n  registry_id: plan_007_redocred_rsft_eval_r5\n- id: plan_016\n  claim: 2\n  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心\n    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO\n    QLoRA 是否也出现 catastrophic forgetting。'\n  priority: P0\n  gpu_budget_hours: 40\n  deps: []\n  registry_id: plan_016_llama_rsft_candidates\n- id: plan_008\n  claim: 2\n  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格\n    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'\n  priority: P1\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: reeval_rsft_topk3\n- id: plan_011\n  claim: 3\n  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward\n    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要\n    gradient_accumulation 适配显存。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_011_bf16_g8_step_eval\n- id: plan_012\n  claim: 3\n  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred\n    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求\n    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'\n  priority: P0\n  gpu_budget_hours: 12\n  deps: []\n  registry_id: plan_012_dpo_ced\n- id: plan_013\n  claim: 4\n  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations\n    说明替代。'\n  priority: CANCELLED\n  gpu_budget_hours: 0\n  deps: []\n  registry_id: null\n- id: plan_009\n  claim: 3\n  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward\n    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心\n    figure。数据已有，只需汇总+画图。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: plan_009_dynamics_figure\n- id: plan_010\n  claim: 1\n  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer\n    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'\n  priority: P1\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: null\n- id: plan_014\n  claim: 1\n  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含\n    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream\n    v2 三档一致要求。用于回答\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\"。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_014_sft_no_evidence\n- id: plan_015\n  claim: 2\n  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED\n    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:\n    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream\n    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于\n    plan_011 eval 结果。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_011\n  registry_id: wave1_grpo_bf16_g4\n- id: plan_mvp1\n  claim: 1\n  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing\n    distractor 的能力验证'\n  priority: P0\n  gpu_budget_hours: 1\n  deps: []\n  registry_id: mvp1_ced_signal\n- id: plan_mvp2_sft\n  claim: 1\n  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: mvp2_sft_warmup\n- id: plan_mvp2_rsft\n  claim: 1\n  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部\n    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,\n    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'\n  priority: P0\n  gpu_budget_hours: 20\n  deps:\n  - plan_mvp1\n  - plan_mvp2_sft\n  registry_id: mvp2_rsft_train_r1\n- id: plan_mvp2_grpo\n  claim: 3\n  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1\n    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic\n    forgetting。D031/D033 完整轨迹支撑 Claim 3'\n  priority: P0\n  gpu_budget_hours: 60\n  deps:\n  - plan_mvp2_sft\n  registry_id: mvp2_grpo_ced_lr5e6_r1\n- id: plan_017\n  claim: 3\n  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT\n    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090\n    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'\n  priority: P0\n  gpu_budget_hours: 50\n  deps: []\n  registry_id: null\n- id: plan_018\n  claim: 1\n  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)\n    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt\n    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 \"only Wikipedia domain\"\n    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'\n  priority: P2\n  gpu_budget_hours: 60\n  deps: []\n  registry_id: null\n- id: plan_019\n  claim: 3\n  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补\n    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个\n    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean\n    ± std，scaling claim 有统计力。'\n  priority: P0\n  gpu_budget_hours: 25\n  deps: []\n  registry_id: plan019_1_7b_sft_s43_r2\n  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,\n    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,\n    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA\n    s43/s44。'\n- id: plan_020\n  claim: 3\n  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)\n    output length distribution with vs without evidence (2) truncation rate 差异（1.7B\n    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without\n    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析\n    + 少量补充 eval。'\n  priority: P1\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_021\n  claim: 1\n  description: 'Deep error analysis: 按 relation type / document length / entity count\n    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings\n    的 insight 层——Main 论文解释 why，Findings 只报 what。'\n  priority: P1\n  gpu_budget_hours: 5\n  deps: []\n  registry_id: null\n- id: plan_022\n  claim: 3\n  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT\n    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'\n  priority: P2\n  gpu_budget_hours: 30\n  deps: []\n  registry_id: null\n- id: plan_023\n  claim: 1\n  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative\n    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'\n  priority: P2\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_w3_sft_seeds\n  claim: 1\n  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)\n    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: wave1_sft_4b_s44_eval_r2\n- id: plan_d112\n  claim: 1\n  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).\n    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:\n    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_w3_sft_seeds\n  registry_id: d112_rsft_s44_gen_shard0\n- id: plan_w18_random\n  claim: 1\n  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based\n    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT\n    有效的关键。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: random_rsft_k1_eval\n",
    "structuredPatch": [
      {
        "oldStart": 68,
        "oldLines": 7,
        "newStart": 68,
        "newLines": 7,
        "lines": [
          "   priority: P0",
          "   gpu_budget_hours: 40",
          "   deps: []",
          "-  registry_id: plan_016_llama_rsft_candidates",
          "+  registry_id: plan_016_llama_grpo_qlora",
          " - id: plan_008",
          "   claim: 2",
          "   description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Edit · `toolu_01WPqracVWC4UgbbVVuPN6vU`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
  "old_string": "  registry_id: mvp2_grpo_ced_lr5e6_r1",
  "new_string": "  registry_id: mvp2_grpo_ced_kl001_r4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "39fe7ec6-6d06-40ab-9e1f-4ebe7a0a0249",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013wYKn9CmZtDEaJhR229Tyb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6730,
      "cache_read_input_tokens": 56128,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6730
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-19T05:46:15.257Z_

<details><summary>↩ Tool result · `toolu_01WPqracVWC4UgbbVVuPN6vU`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "c30614a5-c74a-4b98-b933-7e81ea9b410f",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
    "oldString": "  registry_id: mvp2_grpo_ced_lr5e6_r1",
    "newString": "  registry_id: mvp2_grpo_ced_kl001_r4",
    "originalFile": "experiments:\n- id: plan_001\n  claim: 2\n  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选\n    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py\n    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'\n  priority: P0\n  gpu_budget_hours: 20\n  deps: []\n  registry_id: eval_flat_nli_seed45\n- id: plan_002\n  claim: 1\n  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set\n    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'\n  priority: P0\n  gpu_budget_hours: 4\n  deps:\n  - plan_001\n  registry_id: plan_002_test_rsft_s44\n- id: plan_003\n  claim: 4\n  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing\n    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_001\n  registry_id: plan_003_edcr_diagnostic\n- id: plan_004\n  claim: 1\n  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)\n    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_004_dreeam_baseline\n- id: plan_005\n  claim: 1\n  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'\n  priority: P1\n  gpu_budget_hours: 6\n  deps: []\n  registry_id: mvp2_ced_reranker_poc\n- id: plan_006\n  claim: 1\n  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT\n    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope\n    不足问题。'\n  priority: P0\n  gpu_budget_hours: 32\n  deps: []\n  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3\n- id: plan_007\n  claim: 1\n  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config\n    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%\n    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的\n    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'\n  priority: P0\n  gpu_budget_hours: 16\n  deps: []\n  registry_id: plan_007_redocred_rsft_eval_r5\n- id: plan_016\n  claim: 2\n  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心\n    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO\n    QLoRA 是否也出现 catastrophic forgetting。'\n  priority: P0\n  gpu_budget_hours: 40\n  deps: []\n  registry_id: plan_016_llama_grpo_qlora\n- id: plan_008\n  claim: 2\n  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格\n    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'\n  priority: P1\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: reeval_rsft_topk3\n- id: plan_011\n  claim: 3\n  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward\n    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要\n    gradient_accumulation 适配显存。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_011_bf16_g8_step_eval\n- id: plan_012\n  claim: 3\n  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred\n    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求\n    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'\n  priority: P0\n  gpu_budget_hours: 12\n  deps: []\n  registry_id: plan_012_dpo_ced\n- id: plan_013\n  claim: 4\n  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations\n    说明替代。'\n  priority: CANCELLED\n  gpu_budget_hours: 0\n  deps: []\n  registry_id: null\n- id: plan_009\n  claim: 3\n  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward\n    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心\n    figure。数据已有，只需汇总+画图。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: plan_009_dynamics_figure\n- id: plan_010\n  claim: 1\n  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer\n    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'\n  priority: P1\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: null\n- id: plan_014\n  claim: 1\n  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含\n    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream\n    v2 三档一致要求。用于回答\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\"。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_014_sft_no_evidence\n- id: plan_015\n  claim: 2\n  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED\n    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:\n    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream\n    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于\n    plan_011 eval 结果。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_011\n  registry_id: wave1_grpo_bf16_g4\n- id: plan_mvp1\n  claim: 1\n  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing\n    distractor 的能力验证'\n  priority: P0\n  gpu_budget_hours: 1\n  deps: []\n  registry_id: mvp1_ced_signal\n- id: plan_mvp2_sft\n  claim: 1\n  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: mvp2_sft_warmup\n- id: plan_mvp2_rsft\n  claim: 1\n  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部\n    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,\n    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'\n  priority: P0\n  gpu_budget_hours: 20\n  deps:\n  - plan_mvp1\n  - plan_mvp2_sft\n  registry_id: mvp2_rsft_train_r1\n- id: plan_mvp2_grpo\n  claim: 3\n  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1\n    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic\n    forgetting。D031/D033 完整轨迹支撑 Claim 3'\n  priority: P0\n  gpu_budget_hours: 60\n  deps:\n  - plan_mvp2_sft\n  registry_id: mvp2_grpo_ced_lr5e6_r1\n- id: plan_017\n  claim: 3\n  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT\n    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090\n    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'\n  priority: P0\n  gpu_budget_hours: 50\n  deps: []\n  registry_id: null\n- id: plan_018\n  claim: 1\n  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)\n    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt\n    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 \"only Wikipedia domain\"\n    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'\n  priority: P2\n  gpu_budget_hours: 60\n  deps: []\n  registry_id: null\n- id: plan_019\n  claim: 3\n  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补\n    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个\n    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean\n    ± std，scaling claim 有统计力。'\n  priority: P0\n  gpu_budget_hours: 25\n  deps: []\n  registry_id: plan019_1_7b_sft_s43_r2\n  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,\n    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,\n    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA\n    s43/s44。'\n- id: plan_020\n  claim: 3\n  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)\n    output length distribution with vs without evidence (2) truncation rate 差异（1.7B\n    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without\n    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析\n    + 少量补充 eval。'\n  priority: P1\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_021\n  claim: 1\n  description: 'Deep error analysis: 按 relation type / document length / entity count\n    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings\n    的 insight 层——Main 论文解释 why，Findings 只报 what。'\n  priority: P1\n  gpu_budget_hours: 5\n  deps: []\n  registry_id: null\n- id: plan_022\n  claim: 3\n  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT\n    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'\n  priority: P2\n  gpu_budget_hours: 30\n  deps: []\n  registry_id: null\n- id: plan_023\n  claim: 1\n  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative\n    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'\n  priority: P2\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_w3_sft_seeds\n  claim: 1\n  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)\n    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: wave1_sft_4b_s44_eval_r2\n- id: plan_d112\n  claim: 1\n  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).\n    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:\n    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_w3_sft_seeds\n  registry_id: d112_rsft_s44_gen_shard0\n- id: plan_w18_random\n  claim: 1\n  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based\n    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT\n    有效的关键。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: random_rsft_k1_eval\n",
    "structuredPatch": [
      {
        "oldStart": 176,
        "oldLines": 7,
        "newStart": 176,
        "newLines": 7,
        "lines": [
          "   gpu_budget_hours: 60",
          "   deps:",
          "   - plan_mvp2_sft",
          "-  registry_id: mvp2_grpo_ced_lr5e6_r1",
          "+  registry_id: mvp2_grpo_ced_kl001_r4",
          " - id: plan_017",
          "   claim: 3",
          "   description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Edit · `toolu_015Deasf8g95rHRi7UWEd8MU`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
  "old_string": "  deps: []\n  registry_id: null\n- id: plan_018",
  "new_string": "  deps: []\n  registry_id: plan017_14b_sft\n- id: plan_018"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "b2616ebd-8182-48bc-9ff8-d8160218b586",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015H1TcbcdMJZmWr6H57bjmr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 234,
      "cache_read_input_tokens": 62858,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 234
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-19T05:46:18.586Z_

<details><summary>↩ Tool result · `toolu_015Deasf8g95rHRi7UWEd8MU`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "11fd6249-08f3-4631-9212-55df27baed81",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
    "oldString": "  deps: []\n  registry_id: null\n- id: plan_018",
    "newString": "  deps: []\n  registry_id: plan017_14b_sft\n- id: plan_018",
    "originalFile": "experiments:\n- id: plan_001\n  claim: 2\n  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选\n    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py\n    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'\n  priority: P0\n  gpu_budget_hours: 20\n  deps: []\n  registry_id: eval_flat_nli_seed45\n- id: plan_002\n  claim: 1\n  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set\n    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'\n  priority: P0\n  gpu_budget_hours: 4\n  deps:\n  - plan_001\n  registry_id: plan_002_test_rsft_s44\n- id: plan_003\n  claim: 4\n  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing\n    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_001\n  registry_id: plan_003_edcr_diagnostic\n- id: plan_004\n  claim: 1\n  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)\n    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_004_dreeam_baseline\n- id: plan_005\n  claim: 1\n  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'\n  priority: P1\n  gpu_budget_hours: 6\n  deps: []\n  registry_id: mvp2_ced_reranker_poc\n- id: plan_006\n  claim: 1\n  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT\n    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope\n    不足问题。'\n  priority: P0\n  gpu_budget_hours: 32\n  deps: []\n  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3\n- id: plan_007\n  claim: 1\n  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config\n    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%\n    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的\n    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'\n  priority: P0\n  gpu_budget_hours: 16\n  deps: []\n  registry_id: plan_007_redocred_rsft_eval_r5\n- id: plan_016\n  claim: 2\n  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心\n    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO\n    QLoRA 是否也出现 catastrophic forgetting。'\n  priority: P0\n  gpu_budget_hours: 40\n  deps: []\n  registry_id: plan_016_llama_grpo_qlora\n- id: plan_008\n  claim: 2\n  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格\n    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'\n  priority: P1\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: reeval_rsft_topk3\n- id: plan_011\n  claim: 3\n  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward\n    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要\n    gradient_accumulation 适配显存。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_011_bf16_g8_step_eval\n- id: plan_012\n  claim: 3\n  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred\n    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求\n    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'\n  priority: P0\n  gpu_budget_hours: 12\n  deps: []\n  registry_id: plan_012_dpo_ced\n- id: plan_013\n  claim: 4\n  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations\n    说明替代。'\n  priority: CANCELLED\n  gpu_budget_hours: 0\n  deps: []\n  registry_id: null\n- id: plan_009\n  claim: 3\n  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward\n    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心\n    figure。数据已有，只需汇总+画图。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: plan_009_dynamics_figure\n- id: plan_010\n  claim: 1\n  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer\n    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'\n  priority: P1\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: null\n- id: plan_014\n  claim: 1\n  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含\n    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream\n    v2 三档一致要求。用于回答\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\"。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_014_sft_no_evidence\n- id: plan_015\n  claim: 2\n  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED\n    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:\n    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream\n    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于\n    plan_011 eval 结果。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_011\n  registry_id: wave1_grpo_bf16_g4\n- id: plan_mvp1\n  claim: 1\n  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing\n    distractor 的能力验证'\n  priority: P0\n  gpu_budget_hours: 1\n  deps: []\n  registry_id: mvp1_ced_signal\n- id: plan_mvp2_sft\n  claim: 1\n  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: mvp2_sft_warmup\n- id: plan_mvp2_rsft\n  claim: 1\n  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部\n    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,\n    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'\n  priority: P0\n  gpu_budget_hours: 20\n  deps:\n  - plan_mvp1\n  - plan_mvp2_sft\n  registry_id: mvp2_rsft_train_r1\n- id: plan_mvp2_grpo\n  claim: 3\n  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1\n    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic\n    forgetting。D031/D033 完整轨迹支撑 Claim 3'\n  priority: P0\n  gpu_budget_hours: 60\n  deps:\n  - plan_mvp2_sft\n  registry_id: mvp2_grpo_ced_kl001_r4\n- id: plan_017\n  claim: 3\n  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT\n    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090\n    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'\n  priority: P0\n  gpu_budget_hours: 50\n  deps: []\n  registry_id: null\n- id: plan_018\n  claim: 1\n  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)\n    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt\n    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 \"only Wikipedia domain\"\n    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'\n  priority: P2\n  gpu_budget_hours: 60\n  deps: []\n  registry_id: null\n- id: plan_019\n  claim: 3\n  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补\n    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个\n    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean\n    ± std，scaling claim 有统计力。'\n  priority: P0\n  gpu_budget_hours: 25\n  deps: []\n  registry_id: plan019_1_7b_sft_s43_r2\n  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,\n    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,\n    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA\n    s43/s44。'\n- id: plan_020\n  claim: 3\n  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)\n    output length distribution with vs without evidence (2) truncation rate 差异（1.7B\n    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without\n    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析\n    + 少量补充 eval。'\n  priority: P1\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_021\n  claim: 1\n  description: 'Deep error analysis: 按 relation type / document length / entity count\n    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings\n    的 insight 层——Main 论文解释 why，Findings 只报 what。'\n  priority: P1\n  gpu_budget_hours: 5\n  deps: []\n  registry_id: null\n- id: plan_022\n  claim: 3\n  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT\n    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'\n  priority: P2\n  gpu_budget_hours: 30\n  deps: []\n  registry_id: null\n- id: plan_023\n  claim: 1\n  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative\n    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'\n  priority: P2\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_w3_sft_seeds\n  claim: 1\n  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)\n    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: wave1_sft_4b_s44_eval_r2\n- id: plan_d112\n  claim: 1\n  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).\n    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:\n    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_w3_sft_seeds\n  registry_id: d112_rsft_s44_gen_shard0\n- id: plan_w18_random\n  claim: 1\n  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based\n    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT\n    有效的关键。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: random_rsft_k1_eval\n",
    "structuredPatch": [
      {
        "oldStart": 185,
        "oldLines": 7,
        "newStart": 185,
        "newLines": 7,
        "lines": [
          "   priority: P0",
          "   gpu_budget_hours: 50",
          "   deps: []",
          "-  registry_id: null",
          "+  registry_id: plan017_14b_sft",
          " - id: plan_018",
          "   claim: 1",
          "   description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Edit · `toolu_016M8Vt3nZhjqebTAT1RBvwM`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
  "old_string": "  registry_id: plan019_1_7b_sft_s43_r2",
  "new_string": "  registry_id: plan019_1_7b_rsft_s44_r2"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "c01bb8bc-624b-48ca-bbfc-95b7e1e9d044",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHAyHRFsxNVUMBh7Ci5fQn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 234,
      "cache_read_input_tokens": 63092,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 234
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-19T05:46:21.947Z_

<details><summary>↩ Tool result · `toolu_016M8Vt3nZhjqebTAT1RBvwM`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "07397b90-f0b3-473a-a7a7-8a601d3d4fa1",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
    "oldString": "  registry_id: plan019_1_7b_sft_s43_r2",
    "newString": "  registry_id: plan019_1_7b_rsft_s44_r2",
    "originalFile": "experiments:\n- id: plan_001\n  claim: 2\n  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选\n    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py\n    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'\n  priority: P0\n  gpu_budget_hours: 20\n  deps: []\n  registry_id: eval_flat_nli_seed45\n- id: plan_002\n  claim: 1\n  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set\n    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'\n  priority: P0\n  gpu_budget_hours: 4\n  deps:\n  - plan_001\n  registry_id: plan_002_test_rsft_s44\n- id: plan_003\n  claim: 4\n  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing\n    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_001\n  registry_id: plan_003_edcr_diagnostic\n- id: plan_004\n  claim: 1\n  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)\n    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_004_dreeam_baseline\n- id: plan_005\n  claim: 1\n  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'\n  priority: P1\n  gpu_budget_hours: 6\n  deps: []\n  registry_id: mvp2_ced_reranker_poc\n- id: plan_006\n  claim: 1\n  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT\n    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope\n    不足问题。'\n  priority: P0\n  gpu_budget_hours: 32\n  deps: []\n  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3\n- id: plan_007\n  claim: 1\n  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config\n    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%\n    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的\n    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'\n  priority: P0\n  gpu_budget_hours: 16\n  deps: []\n  registry_id: plan_007_redocred_rsft_eval_r5\n- id: plan_016\n  claim: 2\n  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心\n    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO\n    QLoRA 是否也出现 catastrophic forgetting。'\n  priority: P0\n  gpu_budget_hours: 40\n  deps: []\n  registry_id: plan_016_llama_grpo_qlora\n- id: plan_008\n  claim: 2\n  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格\n    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'\n  priority: P1\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: reeval_rsft_topk3\n- id: plan_011\n  claim: 3\n  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward\n    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要\n    gradient_accumulation 适配显存。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_011_bf16_g8_step_eval\n- id: plan_012\n  claim: 3\n  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred\n    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求\n    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'\n  priority: P0\n  gpu_budget_hours: 12\n  deps: []\n  registry_id: plan_012_dpo_ced\n- id: plan_013\n  claim: 4\n  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations\n    说明替代。'\n  priority: CANCELLED\n  gpu_budget_hours: 0\n  deps: []\n  registry_id: null\n- id: plan_009\n  claim: 3\n  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward\n    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心\n    figure。数据已有，只需汇总+画图。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: plan_009_dynamics_figure\n- id: plan_010\n  claim: 1\n  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer\n    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'\n  priority: P1\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: null\n- id: plan_014\n  claim: 1\n  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含\n    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream\n    v2 三档一致要求。用于回答\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\"。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_014_sft_no_evidence\n- id: plan_015\n  claim: 2\n  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED\n    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:\n    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream\n    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于\n    plan_011 eval 结果。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_011\n  registry_id: wave1_grpo_bf16_g4\n- id: plan_mvp1\n  claim: 1\n  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing\n    distractor 的能力验证'\n  priority: P0\n  gpu_budget_hours: 1\n  deps: []\n  registry_id: mvp1_ced_signal\n- id: plan_mvp2_sft\n  claim: 1\n  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: mvp2_sft_warmup\n- id: plan_mvp2_rsft\n  claim: 1\n  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部\n    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,\n    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'\n  priority: P0\n  gpu_budget_hours: 20\n  deps:\n  - plan_mvp1\n  - plan_mvp2_sft\n  registry_id: mvp2_rsft_train_r1\n- id: plan_mvp2_grpo\n  claim: 3\n  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1\n    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic\n    forgetting。D031/D033 完整轨迹支撑 Claim 3'\n  priority: P0\n  gpu_budget_hours: 60\n  deps:\n  - plan_mvp2_sft\n  registry_id: mvp2_grpo_ced_kl001_r4\n- id: plan_017\n  claim: 3\n  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT\n    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090\n    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'\n  priority: P0\n  gpu_budget_hours: 50\n  deps: []\n  registry_id: plan017_14b_sft\n- id: plan_018\n  claim: 1\n  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)\n    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt\n    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 \"only Wikipedia domain\"\n    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'\n  priority: P2\n  gpu_budget_hours: 60\n  deps: []\n  registry_id: null\n- id: plan_019\n  claim: 3\n  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补\n    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个\n    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean\n    ± std，scaling claim 有统计力。'\n  priority: P0\n  gpu_budget_hours: 25\n  deps: []\n  registry_id: plan019_1_7b_sft_s43_r2\n  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,\n    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,\n    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA\n    s43/s44。'\n- id: plan_020\n  claim: 3\n  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)\n    output length distribution with vs without evidence (2) truncation rate 差异（1.7B\n    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without\n    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析\n    + 少量补充 eval。'\n  priority: P1\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_021\n  claim: 1\n  description: 'Deep error analysis: 按 relation type / document length / entity count\n    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings\n    的 insight 层——Main 论文解释 why，Findings 只报 what。'\n  priority: P1\n  gpu_budget_hours: 5\n  deps: []\n  registry_id: null\n- id: plan_022\n  claim: 3\n  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT\n    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'\n  priority: P2\n  gpu_budget_hours: 30\n  deps: []\n  registry_id: null\n- id: plan_023\n  claim: 1\n  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative\n    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'\n  priority: P2\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_w3_sft_seeds\n  claim: 1\n  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)\n    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: wave1_sft_4b_s44_eval_r2\n- id: plan_d112\n  claim: 1\n  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).\n    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:\n    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_w3_sft_seeds\n  registry_id: d112_rsft_s44_gen_shard0\n- id: plan_w18_random\n  claim: 1\n  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based\n    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT\n    有效的关键。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: random_rsft_k1_eval\n",
    "structuredPatch": [
      {
        "oldStart": 205,
        "oldLines": 7,
        "newStart": 205,
        "newLines": 7,
        "lines": [
          "   priority: P0",
          "   gpu_budget_hours: 25",
          "   deps: []",
          "-  registry_id: plan019_1_7b_sft_s43_r2",
          "+  registry_id: plan019_1_7b_rsft_s44_r2",
          "   notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,",
          "     mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,",
          "     std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Edit · `toolu_01TwGd727hHdNLTdAq1gNLWr`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
  "old_string": "  registry_id: d112_rsft_s44_gen_shard0",
  "new_string": "  registry_id: d112_rsft_s44_train"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "ae653527-ec64-4ef4-9484-bc71b108039e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KcN4gbatJkTCz3UER6CU4u",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 233,
      "cache_read_input_tokens": 63326,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 233
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-19T05:46:25.310Z_

<details><summary>↩ Tool result · `toolu_01TwGd727hHdNLTdAq1gNLWr`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "b38951c4-2845-4924-b2d6-81d1acadf35d",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/experiment_plan.yaml",
    "oldString": "  registry_id: d112_rsft_s44_gen_shard0",
    "newString": "  registry_id: d112_rsft_s44_train",
    "originalFile": "experiments:\n- id: plan_001\n  claim: 2\n  description: 'CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选\n    RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py\n    用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。'\n  priority: P0\n  gpu_budget_hours: 20\n  deps: []\n  registry_id: eval_flat_nli_seed45\n- id: plan_002\n  claim: 1\n  description: 'Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set\n    上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。'\n  priority: P0\n  gpu_budget_hours: 4\n  deps:\n  - plan_001\n  registry_id: plan_002_test_rsft_s44\n- id: plan_003\n  claim: 4\n  description: 'EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing\n    方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps:\n  - plan_001\n  registry_id: plan_003_edcr_diagnostic\n- id: plan_004\n  claim: 1\n  description: 'DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large)\n    的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_004_dreeam_baseline\n- id: plan_005\n  claim: 1\n  description: 'CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。'\n  priority: P1\n  gpu_budget_hours: 6\n  deps: []\n  registry_id: mvp2_ced_reranker_poc\n- id: plan_006\n  claim: 1\n  description: 'Model size ablation (D077 升 P0): Qwen3-1.7B 和 Qwen3-8B 上复现 SFT → RSFT\n    → eval pipeline，验证 evidence tax + RSFT 增益 + decoupling 在不同模型规模下成立。应对 RC4 和 scope\n    不足问题。'\n  priority: P0\n  gpu_budget_hours: 32\n  deps: []\n  registry_id: plan_006_qwen3_1_7b_no_evidence_eval_v3\n- id: plan_007\n  claim: 1\n  description: 'Re-DocRED cross-dataset (D077 升 P0): 在 Re-DocRED 上用当前 best config\n    做 SFT → RSFT → eval。数据已就绪（格式与 DocRED 兼容，96 relation types 一致）。⚠️ Re-DocRED ~55%\n    triples 无 evidence 标注（修正的 false negative），必须报告两种模式：evidence_only（与 DocRED 可比的\n    evi_f1，仅 43% triples）+ full（全部 triples 的 rel_f1，无 evi_f1）。转换脚本已支持 --mode full。'\n  priority: P0\n  gpu_budget_hours: 16\n  deps: []\n  registry_id: plan_007_redocred_rsft_eval_r5\n- id: plan_016\n  claim: 2\n  description: 'LLaMA-3.1-8B cross-family validation (D077 新增): 在非 Qwen 家族模型上复现核心\n    pipeline (SFT → RSFT → GRPO QLoRA)，验证 decoupling spectrum 跨模型家族成立。关键实验：LLaMA GRPO\n    QLoRA 是否也出现 catastrophic forgetting。'\n  priority: P0\n  gpu_budget_hours: 40\n  deps: []\n  registry_id: plan_016_llama_grpo_qlora\n- id: plan_008\n  claim: 2\n  description: 'top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格\n    ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。'\n  priority: P1\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: reeval_rsft_topk3\n- id: plan_011\n  claim: 3\n  description: 'GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward\n    + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要\n    gradient_accumulation 适配显存。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_011_bf16_g8_step_eval\n- id: plan_012\n  claim: 3\n  description: 'DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred\n    vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求\n    DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。'\n  priority: P0\n  gpu_budget_hours: 12\n  deps: []\n  registry_id: plan_012_dpo_ced\n- id: plan_013\n  claim: 4\n  description: '[CANCELLED by D104] EDCR 人工标注验证: 用户决定不做。RC6 用 per-relation 分析 + Limitations\n    说明替代。'\n  priority: CANCELLED\n  gpu_budget_hours: 0\n  deps: []\n  registry_id: null\n- id: plan_009\n  claim: 3\n  description: 'GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward\n    轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心\n    figure。数据已有，只需汇总+画图。'\n  priority: P0\n  gpu_budget_hours: 2\n  deps: []\n  registry_id: plan_009_dynamics_figure\n- id: plan_010\n  claim: 1\n  description: 'NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer\n    的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。D104 升级。'\n  priority: P1\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: null\n- id: plan_014\n  claim: 1\n  description: 'SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含\n    evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream\n    v2 三档一致要求。用于回答\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\"。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: plan_014_sft_no_evidence\n- id: plan_015\n  claim: 2\n  description: 'bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED\n    reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的:\n    隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream\n    v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于\n    plan_011 eval 结果。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_011\n  registry_id: wave1_grpo_bf16_g4\n- id: plan_mvp1\n  claim: 1\n  description: 'MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing\n    distractor 的能力验证'\n  priority: P0\n  gpu_budget_hours: 1\n  deps: []\n  registry_id: mvp1_ced_signal\n- id: plan_mvp2_sft\n  claim: 1\n  description: 'SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线'\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: mvp2_sft_warmup\n- id: plan_mvp2_rsft\n  claim: 1\n  description: 'RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部\n    PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087,\n    r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128'\n  priority: P0\n  gpu_budget_hours: 20\n  deps:\n  - plan_mvp1\n  - plan_mvp2_sft\n  registry_id: mvp2_rsft_train_r1\n- id: plan_mvp2_grpo\n  claim: 3\n  description: 'GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1\n    max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic\n    forgetting。D031/D033 完整轨迹支撑 Claim 3'\n  priority: P0\n  gpu_budget_hours: 60\n  deps:\n  - plan_mvp2_sft\n  registry_id: mvp2_grpo_ced_kl001_r4\n- id: plan_017\n  claim: 3\n  description: 'Qwen3-14B scaling study: SFT(with-evidence) + SFT(no-evidence) + RSFT\n    + eval。 第 4 尺度档位（1.7B/4B/8B/14B），验证 evidence tax 在更大模型上是否继续趋近零或转正。 需评估 RTX 5090\n    32GB 显存是否够 bf16 LoRA（14B×2=28GB base），不够则用 QLoRA。 至少 2 seeds。'\n  priority: P0\n  gpu_budget_hours: 50\n  deps: []\n  registry_id: plan017_14b_sft\n- id: plan_018\n  claim: 1\n  description: 'Cross-domain DocRE validation: 在 CDR (Chemical-Disease Relations)\n    或 GDA (Gene-Disease Associations) 等生物医学 DocRE 数据集上验证 FREIGE pipeline。 需要：数据格式适配、prompt\n    模板调整、relation type 映射。 验证 evidence-grounded DocRE 跨领域泛化能力，回应 \"only Wikipedia domain\"\n    审稿质疑。 ⚠️ CDR/GDA 均无 evidence sentence 标注，无法计算 evi_f1。降级 P2，Limitations 说明。'\n  priority: P2\n  gpu_budget_hours: 60\n  deps: []\n  registry_id: null\n- id: plan_019\n  claim: 3\n  description: 'Scaling seeds supplement: 每个尺度补到 3+ seeds（k=1 RSFT）。 当前缺口：1.7B 需补\n    s43/s44，LLaMA 需补 s43/s44。 4B 已有 4+ seeds 不需补。8B-Qwen 2-seed 已完成（s42+s44）。每个\n    seed 含 SFT + RSFT + no-evidence eval ≈ 5 GPU-h。 目标：每个尺度的 evidence tax 有 mean\n    ± std，scaling claim 有统计力。'\n  priority: P0\n  gpu_budget_hours: 25\n  deps: []\n  registry_id: plan019_1_7b_rsft_s44_r2\n  notes: '8B-Qwen RSFT 2-seed 完成 (2026-05-19): s42 ign_f1=0.5376, s44 ign_f1=0.5451,\n    mean=0.5414, sample_std=0.53pp。SFT baseline: s42=0.5051, s44=0.4681, mean=0.4866,\n    std=2.62pp。RSFT 将 seed variance 从 2.62pp 压缩到 0.53pp (~5x)。剩余：1.7B s43/s44, LLaMA\n    s43/s44。'\n- id: plan_020\n  claim: 3\n  description: 'Evidence tax mechanistic analysis: 解释 WHY 1.7B 获益而 4B 受损。 分析维度：(1)\n    output length distribution with vs without evidence (2) truncation rate 差异（1.7B\n    fair subset 已有基础） (3) hallucination rate（false positive relations 在 with/without\n    evidence 中的比例） (4) per-document evidence 生成对 RE 的影响（按 doc length 分层） 主要是 CPU 分析\n    + 少量补充 eval。'\n  priority: P1\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_021\n  claim: 1\n  description: 'Deep error analysis: 按 relation type / document length / entity count\n    / evidence distance 分层分析。扩展 D070 per-relation EDCR 分析到更多维度。 区分 Main 和 Findings\n    的 insight 层——Main 论文解释 why，Findings 只报 what。'\n  priority: P1\n  gpu_budget_hours: 5\n  deps: []\n  registry_id: null\n- id: plan_022\n  claim: 3\n  description: 'Third model family validation: Mistral-7B 或 Gemma-2-9B 上复现 SFT + RSFT\n    + eval。 验证 scaling pattern 跨第三个模型家族成立。如果 14B（plan_017）已做则优先级下降。'\n  priority: P2\n  gpu_budget_hours: 30\n  deps: []\n  registry_id: null\n- id: plan_023\n  claim: 1\n  description: 'DocKS-RAG / LMRC baseline reproduction: 在相同 eval protocol 下复现 generative\n    DocRE SOTA（DocKS-RAG, LMRC）作为完整对比表。审稿人期望 same-condition comparison。'\n  priority: P2\n  gpu_budget_hours: 10\n  deps: []\n  registry_id: null\n- id: plan_w3_sft_seeds\n  claim: 1\n  description: W3 修复：SFT 4B baseline seed43 + seed44 训练 + eval。 与 canonical SFT (seed42)\n    配对，计算 bootstrap CI + Cohen d， 验证 RSFT +4.92pp 增益的统计显著性。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 8\n  deps: []\n  registry_id: wave1_sft_4b_s44_eval_r2\n- id: plan_d112\n  claim: 1\n  description: 'D112: Full RSFT pipeline from SFT s44 base (strongest seed, ign_f1=0.4734).\n    所有现有 4B RSFT 都基于 SFT s42 (最弱 seed)。验证 RSFT 是否能在强 SFT base 上也产生提升。Steps:\n    generate candidates (N=8) → CED score → k=1 filter → RSFT train → D076 eval。'\n  priority: P0\n  gpu_budget_hours: 8\n  deps:\n  - plan_w3_sft_seeds\n  registry_id: d112_rsft_s44_gen_shard0\n- id: plan_w18_random\n  claim: 1\n  description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based\n    selection 的价值。如果 random 也提升 → NLI scoring 不关键； 如果 random 不提升 → NLI scoring 是 RSFT\n    有效的关键。Wave 1 实验。\n  priority: P0\n  gpu_budget_hours: 4\n  deps: []\n  registry_id: random_rsft_k1_eval\n",
    "structuredPatch": [
      {
        "oldStart": 263,
        "oldLines": 7,
        "newStart": 263,
        "newLines": 7,
        "lines": [
          "   gpu_budget_hours: 8",
          "   deps:",
          "   - plan_w3_sft_seeds",
          "-  registry_id: d112_rsft_s44_gen_shard0",
          "+  registry_id: d112_rsft_s44_train",
          " - id: plan_w18_random",
          "   claim: 1",
          "   description: W18 修复：Random k=1 RSFT baseline。从 k=1 候选中随机抽取（不用 NLI 分数）， 验证 NLI-based"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 33_

5 处 registry_id 已全部更新。验证结果：

| plan_id | 旧值 | 新值 | 原因 |
|---------|------|------|------|
| plan_016 | `plan_016_llama_rsft_candidates` (failed) | `plan_016_llama_grpo_qlora` (DONE/success) | 旧值指向失败的初始 candidate gen，GRPO 实验是该 plan 的核心验证 |
| plan_mvp2_grpo | `mvp2_grpo_ced_lr5e6_r1` (killed) | `mvp2_grpo_ced_kl001_r4` (DONE/success) | 旧值被 kill，r4 是完整跑完的 QLoRA GRPO 实验 |
| plan_017 | null | `plan017_14b_sft` (RUNNING) | 14B SFT 已提交运行 |
| plan_019 | `plan019_1_7b_sft_s43_r2` (DONE) | `plan019_1_7b_rsft_s44_r2` (RUNNING) | SFT 步骤已完成，当前最新进展是 1.7B RSFT 重跑 |
| plan_d112 | `d112_rsft_s44_gen_shard0` (DONE) | `d112_rsft_s44_train` (RUNNING) | gen+CED score 步骤已完成，当前最新步骤是 RSFT train |

其余 20 个 plan 的 registry_id 与 registry 一致，无需更新。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "uuid": "1dad13b6-8bc1-4cac-983c-3eda12703e52",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QUgFk3SwraiBpC18LtmaC4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 225,
      "cache_read_input_tokens": 63559,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 225
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Task result

_source line 34_

5 处 registry_id 已全部更新。验证结果：

| plan_id | 旧值 | 新值 | 原因 |
|---------|------|------|------|
| plan_016 | `plan_016_llama_rsft_candidates` (failed) | `plan_016_llama_grpo_qlora` (DONE/success) | 旧值指向失败的初始 candidate gen，GRPO 实验是该 plan 的核心验证 |
| plan_mvp2_grpo | `mvp2_grpo_ced_lr5e6_r1` (killed) | `mvp2_grpo_ced_kl001_r4` (DONE/success) | 旧值被 kill，r4 是完整跑完的 QLoRA GRPO 实验 |
| plan_017 | null | `plan017_14b_sft` (RUNNING) | 14B SFT 已提交运行 |
| plan_019 | `plan019_1_7b_sft_s43_r2` (DONE) | `plan019_1_7b_rsft_s44_r2` (RUNNING) | SFT 步骤已完成，当前最新进展是 1.7B RSFT 重跑 |
| plan_d112 | `d112_rsft_s44_gen_shard0` (DONE) | `d112_rsft_s44_train` (RUNNING) | gen+CED score 步骤已完成，当前最新步骤是 RSFT train |

其余 20 个 plan 的 registry_id 与 registry 一致，无需更新。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 154696,
  "duration_api_ms": 154590,
  "num_turns": 12,
  "stop_reason": "end_turn",
  "session_id": "634a5108-09f6-4d84-84f8-5d5a864789c4",
  "total_cost_usd": 0.7673832500000001,
  "usage": {
    "input_tokens": 14,
    "cache_creation_input_tokens": 52337,
    "cache_read_input_tokens": 450106,
    "output_tokens": 8530,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 52337,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 446,
        "cache_read_input_tokens": 63559,
        "cache_creation_input_tokens": 225,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 225
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1814,
      "outputTokens": 18,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001904,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 14,
      "outputTokens": 8530,
      "cacheReadInputTokens": 450106,
      "cacheCreationInputTokens": 52337,
      "webSearchRequests": 0,
      "costUSD": 0.76547925,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "97620948-59ce-4e9d-8a3a-3eaeb799629f"
}
```

</details>

---

# analysis rho02 adaptive tau09 r2

**When Does Detect-and-Reweight Work for Synthetic Contamination?** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 37
- **Recorded user turns:** 0
- **Tool calls:** 11
- **Original source:** `logs/workers/worker_analysis_rho02_adaptive_tau09_r2_20260517T111817.log`
- **Structured JSON:** [`94bc093161fb2c64f132.json`](../../sessions/94/94bc093161fb2c64f132.json)

## Before a recorded user message

37 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training",
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
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
    "mcp__agent-ml-research__compare_wandb_runs",
    "mcp__agent-ml-research__detect_image",
    "mcp__agent-ml-research__fetch_wandb_metrics",
    "mcp__agent-ml-research__fetch_wandb_run_history",
    "mcp__agent-ml-research__get_best_wandb_run",
    "mcp__agent-ml-research__kill_job",
    "mcp__agent-ml-research__list_wandb_runs",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__ssh_execute",
    "mcp__agent-ml-research__ssh_read_only",
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
  "uuid": "334905d2-1469-4c7a-8d0b-af8ab67155be",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/memory/"
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
    "resetsAt": 1779031800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "6d18a5db-bbf0-45d6-a867-c25dc7ea330c",
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the training log and fetching W&B metrics in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "46ba07c7-4e5f-4851-9a1d-1c530d3bbf4a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ea7ZgTKmECEn8zMubWRJnq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13246,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13246
      },
      "output_tokens": 20,
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

_source line 5_

开始分析实验 rho02_adaptive_tau09_r2。先并行读取日志和 W&B 数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "aa7f0cdb-3878-45cf-8737-48da35513a14",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ea7ZgTKmECEn8zMubWRJnq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13246,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13246
      },
      "output_tokens": 20,
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

_source line 6_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01A8qwv7ZFdTnKiSgVgsZR32`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__fetch_wandb_metrics,mcp__agent-ml-research__list_wandb_runs,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__read_registry",
  "max_results": 6
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "a91278f6-d560-461b-a541-754fc380a555",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ea7ZgTKmECEn8zMubWRJnq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13246,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13246
      },
      "output_tokens": 20,
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

_source line 7 · 2026-05-17T11:18:29.032Z_

<details><summary>↩ Tool result · `toolu_01A8qwv7ZFdTnKiSgVgsZR32`</summary>

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
  "tool_name": "mcp__agent-ml-research__fetch_wandb_metrics"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__list_wandb_runs"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
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
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "8c76f702-c353-407b-a45b-adbcdfc4814e",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__list_wandb_runs",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__fetch_wandb_metrics,mcp__agent-ml-research__list_wandb_runs,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 34
  }
}
```

</details>

---

### Assistant

_source line 8_

<details><summary>Logged reasoning block</summary>

```text
Now let me parallel fetch: 1) the training log, 2) W&B runs list, 3) registry for existing experiments (to find uniform baseline).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "aaa9e81e-4e37-4110-82a0-75f80ebac155",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A3vRDW487UzyaetYTxsb3A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2263,
      "cache_read_input_tokens": 25087,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2263
      },
      "output_tokens": 16,
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

_source line 9_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_011xCd9PYayF56kbSWGb6Tn1`</summary>

```json
{
  "server": "westd-30476",
  "command": "cat ~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "d87d910b-2cc7-494d-883e-e1b297f83204",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A3vRDW487UzyaetYTxsb3A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2263,
      "cache_read_input_tokens": 25087,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2263
      },
      "output_tokens": 16,
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

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__list_wandb_runs · `toolu_015fzN55Rko7PWth63Qf5VNd`</summary>

```json
{
  "project": "provenance_weight_training",
  "filters": {
    "display_name": {
      "$regex": "rho02"
    }
  },
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "dbd9ee74-4580-42cb-a988-8af7c854ed51",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A3vRDW487UzyaetYTxsb3A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2263,
      "cache_read_input_tokens": 25087,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2263
      },
      "output_tokens": 16,
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

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01SVTrBfxSYqr5PSGLZ7aCYJ`</summary>

```json
{
  "project": "provenance_weight_training",
  "filters": {
    "exp_id": "rho02_adaptive_tau09_r2"
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
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "a49d5534-81ce-4104-a045-f74ca6833506",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A3vRDW487UzyaetYTxsb3A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2263,
      "cache_read_input_tokens": 25087,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2263
      },
      "output_tokens": 16,
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

_source line 12 · 2026-05-17T11:18:40.748Z_

<details><summary>↩ Tool result · `toolu_011xCd9PYayF56kbSWGb6Tn1`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\nLoading tokenizer: models/Qwen/Qwen3-0.6B\\nLoading model: models/Qwen/Qwen3-0.6B\\n\\rLoading weights:   0%|          | 0/311 [00:00<?, ?it/s]\\rLoading weights: 100%|██████████| 311/311 [00:00<00:00, 13933.52it/s]\\n[transformers] warmup_ratio is deprecated and will be removed in v5.2. Use `warmup_steps` instead.\\nLoading training data: data/scored_data_rho02.jsonl\\n  206111 examples loaded\\n  num_train_tokens=200000000 → max_steps=6103\\nTraceback (most recent call last):\\n  File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 450, in &lt;module>\\n    main()\\n  File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 400, in main\\n    trainer = WeightedTrainer(\\n              ^^^^^^^^^^^^^^^^\\n  File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 101, in __init__\\n    super().__init__(**kwargs)\\nTypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\\nDONE: rho02_adaptive_tau09 seed42\\nEXIT_CODE=0\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 5.52}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "837e0406-5eba-450c-9c4b-6d6778e7c2f4",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\\\nLoading tokenizer: models/Qwen/Qwen3-0.6B\\\\nLoading model: models/Qwen/Qwen3-0.6B\\\\n\\\\rLoading weights:   0%|          | 0/311 [00:00<?, ?it/s]\\\\rLoading weights: 100%|██████████| 311/311 [00:00<00:00, 13933.52it/s]\\\\n[transformers] warmup_ratio is deprecated and will be removed in v5.2. Use `warmup_steps` instead.\\\\nLoading training data: data/scored_data_rho02.jsonl\\\\n  206111 examples loaded\\\\n  num_train_tokens=200000000 → max_steps=6103\\\\nTraceback (most recent call last):\\\\n  File \\\\\\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\\\\\", line 450, in &lt;module>\\\\n    main()\\\\n  File \\\\\\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\\\\\", line 400, in main\\\\n    trainer = WeightedTrainer(\\\\n              ^^^^^^^^^^^^^^^^\\\\n  File \\\\\\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\\\\\", line 101, in __init__\\\\n    super().__init__(**kwargs)\\\\nTypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\\\\nDONE: rho02_adaptive_tau09 seed42\\\\nEXIT_CODE=0\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 5.52}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"[transformers] `torch_dtype` is deprecated! Use `dtype` instead!\\nLoading tokenizer: models/Qwen/Qwen3-0.6B\\nLoading model: models/Qwen/Qwen3-0.6B\\n\\rLoading weights:   0%|          | 0/311 [00:00<?, ?it/s]\\rLoading weights: 100%|██████████| 311/311 [00:00<00:00, 13933.52it/s]\\n[transformers] warmup_ratio is deprecated and will be removed in v5.2. Use `warmup_steps` instead.\\nLoading training data: data/scored_data_rho02.jsonl\\n  206111 examples loaded\\n  num_train_tokens=200000000 → max_steps=6103\\nTraceback (most recent call last):\\n  File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 450, in &lt;module>\\n    main()\\n  File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 400, in main\\n    trainer = WeightedTrainer(\\n              ^^^^^^^^^^^^^^^^\\n  File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 101, in __init__\\n    super().__init__(**kwargs)\\nTypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\\nDONE: rho02_adaptive_tau09 seed42\\nEXIT_CODE=0\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 5.52}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-17T11:18:40.808Z_

<details><summary>↩ Tool result · reported error · `toolu_015fzN55Rko7PWth63Qf5VNd`</summary>

```text
Error executing tool list_wandb_runs: list_wandb_runs() got an unexpected keyword argument 'wandb_project'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "f16bcd78-726c-4baa-89aa-a06d7d6e5ab9",
  "tool_use_result": "Error: Error executing tool list_wandb_runs: list_wandb_runs() got an unexpected keyword argument 'wandb_project'"
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T11:18:41.768Z_

<details><summary>↩ Tool result · `toolu_01SVTrBfxSYqr5PSGLZ7aCYJ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9288}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "9c7b9821-0c08-44fe-be52-42ba631938dc",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9288}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9288}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

````text
The training log shows a crash - the experiment failed with a TypeError. Let me look more carefully:

```
TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'
DONE: rho02_adaptive_tau09 seed42
EXIT_CODE=0
```

The script crashed with a `TypeError` - the `Trainer.__init__()` got an unexpected keyword argument 'tokenizer'. This is a known issue with newer versions of transformers where `tokenizer` was renamed to `processing_class` or similar.

Despite the crash, the log says "DONE" and "EXIT_CODE=0" which is misleading - the script likely has a try/except or the shell script wrapper is not properly propagating the error code.


The experiment never actually ran - it crashed during initialization before any training could start, so there's no training metrics or evaluation data. Let me check the W&B runs with the corrected parameters and see if there are any other rho02 experiments in the registry.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "e70e99b3-1fce-46f9-bcec-28ddcb2f5919",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fXUkVdeJcMZ8qhDfYwbuV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1057,
      "cache_read_input_tokens": 27350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1057
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

_source line 16_

实验崩溃了。日志显示初始化阶段就报错：`TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'`。没有产出任何训练数据。

让我确认 W&B 上的状态，并查找相关 baseline 实验。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "798a0705-7256-4451-a0c0-a07d55a39535",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fXUkVdeJcMZ8qhDfYwbuV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1057,
      "cache_read_input_tokens": 27350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1057
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

_source line 17_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__list_wandb_runs · `toolu_015PApyB3EF1NEaAehaZeQjV`</summary>

```json
{
  "project": "provenance_weight_training",
  "filters": {
    "display_name": {
      "$regex": "rho02"
    }
  },
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "63ecb5eb-c4d1-488e-b6d3-59e7bf2a16ed",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fXUkVdeJcMZ8qhDfYwbuV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1057,
      "cache_read_input_tokens": 27350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1057
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

_source line 18 · 2026-05-17T11:18:52.360Z_

<details><summary>↩ Tool result · reported error · `toolu_015PApyB3EF1NEaAehaZeQjV`</summary>

```text
Error executing tool list_wandb_runs: list_wandb_runs() got an unexpected keyword argument 'wandb_project'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "787b522f-f680-45b1-8878-2b438809405b",
  "tool_use_result": "Error: Error executing tool list_wandb_runs: list_wandb_runs() got an unexpected keyword argument 'wandb_project'"
}
```

</details>

---

### Tool call

_source line 19_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01RtHHjuda47bPLGALPJZFXQ`</summary>

```json
{
  "project": "provenance_weight_training",
  "limit": 0,
  "fields": [
    "exp_id",
    "status",
    "conclusion",
    "metrics"
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
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "96f94510-c8a4-41e8-98a0-2304ea203ee5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fXUkVdeJcMZ8qhDfYwbuV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1057,
      "cache_read_input_tokens": 27350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1057
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

_source line 20 · 2026-05-17T11:18:53.528Z_

<details><summary>↩ Tool result · `toolu_01RtHHjuda47bPLGALPJZFXQ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"batchsize16_nmin8_r2\": {\"status\": \"QUEUED\"}, \"rho02_adaptive_tau09_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"random_reweight_seed123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"batch_adaptive_tau_rho06_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bs8_auto_nmin_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"batchsize16_nmin8_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rho02_adaptive_tau09_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"batch_adaptive_tau_rho06_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bs8_auto_nmin_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b0_3_seed123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b0_3_seed456\": {\"status\": \"ALLOCATED\"}, \"random_reweight_v2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.83, \"eval_loss_holdout\": 2.8809}}, \"tau_095_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.723, \"eval_loss\": 2.8749, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"train_loss\": 10.198, \"total_steps\": 6103, \"train_runtime_s\": 13699, \"train_samples_per_second\": 7.128, \"b_star_count\": 24412, \"b_star_mean\": 3.0775, \"b_star_median\": 1.52, \"b_star_std\": 3.9923, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.8, \"b_star_p75\": 3.46, \"b_star_pct_zero\": 0, \"b_star_pct_below_0.5\": 8.5, \"b_star_pct_0.5_to_1\": 24.7, \"b_star_pct_1_to_2\": 26.4, \"b_star_pct_above_2\": 40.3}, \"conclusion\": \"negative\"}, \"llama3b_uniform_seed42\": {\"status\": \"RUNNING\"}, \"llama3b_adaptive_seed42\": {\"status\": \"RUNNING\"}, \"hybrid_rho06_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss_holdout\": 2.8637, \"eval_ppl_holdout\": 17.53}}, \"batch_adaptive_tau_rho04_seed42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_loss_holdout\": 2.8725, \"eval_ppl_holdout\": 17.681, \"train_loss\": 9.8206, \"train_runtime_sec\": 45402.86}}, \"p0_contamination_60_datagen\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_lines\": 371499, \"synthetic_count\": 222900, \"human_count\": 148599, \"actual_contamination_ratio\": 0.6, \"q_score_mean\": 0.6243, \"q_score_std\": 0.3703, \"q_score_median\": 0.7753, \"file_size_mb\": 907}}, \"datagen_synthetic_4gpu\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"grid_b5_0_seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.8468, \"total_steps\": 6103, \"train_runtime_s\": 14434, \"gpu_hours\": 4.01, \"eval_ppl_holdout\": 17.8039, \"eval_loss\": 2.8794, \"eval_holdout_tokens\": 4077068}, \"conclusion\": \"success\"}, \"grid_b3_0_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 10.7422, \"total_steps\": 6103, \"train_runtime_s\": 12955.83, \"gpu_hours\": 3.6, \"eval_ppl_holdout\": 17.76, \"eval_loss\": 2.877, \"eval_holdout_tokens\": 4077068}}, \"grid_b2_0_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 10.61, \"total_steps\": 6103, \"train_runtime_s\": 13058.8, \"gpu_hours\": 3.63, \"train_samples_per_second\": 7.478, \"train_steps_per_second\": 0.467, \"eval_ppl_holdout\": 17.725, \"eval_loss\": 2.875, \"eval_holdout_tokens\": 4077068}}, \"grid_b1_5_seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.4776, \"total_steps\": 6103, \"train_runtime_s\": 15053.1, \"gpu_hours\": 4.18, \"eval_ppl_holdout\": 17.701, \"eval_loss\": 2.8736}, \"conclusion\": \"success\"}, \"grid_b1_0_seed123\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.674, \"eval_loss\": 2.8721, \"eval_holdout_tokens\": 4077068, \"train_loss\": 10.218, \"total_steps\": 6103, \"train_runtime_s\": 13878, \"gpu_hours\": 3.88}, \"conclusion\": \"success\"}, \"grid_b0_5_seed123\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.638, \"eval_loss\": 2.87, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.601, \"total_steps\": 6103, \"train_runtime_s\": 13104, \"gpu_hours\": 3.8}, \"conclusion\": \"success\"}, \"ess_only_seed123\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.72, \"eval_loss_holdout\": 2.8746, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\", \"eval_note\": \"Also ran on scored_data.jsonl (train data): ppl=9.66, loss=2.2677, tokens=3029693\", \"train_loss\": 10.2159, \"train_steps\": 6103, \"train_runtime_seconds\": 12959.5, \"b_star_mean\": 3.55, \"b_star_median\": 1.5918, \"b_star_std\": 4.7209, \"b_star_min\": 0.2344, \"b_star_max\": 20, \"b_star_p25\": 0.8398, \"b_star_p75\": 3.8281, \"b_star_p90\": 9.5996, \"b_star_count\": 21971, \"vs_uniform_ppl_delta\": \"+0.034\", \"vs_adaptive_fix_ppl_delta\": \"+0.077\"}, \"conclusion\": \"success\"}, \"hybrid_rho04_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss_holdout\": 2.863, \"eval_ppl_holdout\": 17.514}}, \"grid_b0_2_seed42\": {\"status\": \"RUNNING\", \"conclusion\": \"killed\"}, \"threshold_q03_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss_holdout\": 2.848, \"eval_ppl_holdout\": 17.253}}, \"rho02_uniform_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.336, \"eval_loss_holdout\": 2.853, \"eval_holdout_tokens\": 4077068}}, \"threshold_q07_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"random_reweight_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b0_1_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.657, \"eval_loss_holdout\": 2.871}, \"conclusion\": \"success\"}, \"contamination_60_tau06_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.7359, \"eval_loss_holdout\": 2.8756, \"eval_holdout_tokens\": 4077068, \"train_loss\": 8.9804, \"train_runtime_seconds\": 13367.3, \"train_samples_per_second\": 7.305, \"total_steps\": 6103, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"contamination_60_tau07_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.875, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.358, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"detect_remove_baseline_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.29, \"eval_loss_holdout\": 2.8499, \"eval_holdout_tokens\": 4077068, \"train_loss\": 11.003, \"train_runtime_seconds\": 13248, \"total_steps\": 6103, \"train_samples_per_second\": 7.371}, \"conclusion\": \"success\"}, \"grid_b0_3_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.64, \"eval_loss_holdout\": 2.8702, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"train_loss\": 9.1154, \"train_runtime_seconds\": 13365.79, \"train_samples_per_second\": 7.306, \"total_steps\": 6103, \"b_fixed\": 0.3, \"alpha_eff_typical_range\": \"0.07-0.88\", \"ess_typical_range\": \"2.3-4.0\"}, \"conclusion\": \"success\"}, \"contamination_60_ess_only_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.77, \"eval_loss_holdout\": 2.8775, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.842, \"total_steps\": 6103, \"train_runtime_seconds\": 13152}, \"conclusion\": \"success\"}, \"tau_095_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_09_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"nmin5_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"grid_b5_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.993, \"eval_loss\": 2.89, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.488, \"total_steps\": 6103, \"train_runtime_s\": 6601, \"gpu_hours\": 1.83, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"grid_b3_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.921, \"eval_loss\": 2.886, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.435, \"total_steps\": 6103, \"train_runtime_s\": 6602, \"gpu_hours\": 1.83, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"grid_b2_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.989, \"eval_loss\": 2.8898, \"eval_holdout_tokens\": 4077068, \"train_loss\": 10.625, \"total_steps\": 6103, \"train_runtime_s\": 12969, \"gpu_hours\": 3.6, \"train_samples_per_second\": 7.53, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"ess_only_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl\": 17.719, \"eval_loss\": 2.8746, \"eval_tokens\": 4077068, \"train_loss\": 10.174, \"vs_uniform_ppl_delta\": \"+0.018\", \"vs_adaptive_ppl_delta\": \"+0.077\", \"vs_adaptive_fix_ppl_delta\": \"+0.062\"}, \"conclusion\": \"success\"}, \"ess_only_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl\": 17.73, \"eval_loss\": 2.875, \"b_star_median\": 1.58, \"b_star_mean\": 3.51, \"vs_uniform_ppl_delta\": \"+0.038\", \"vs_adaptive_ppl_delta\": \"+0.08\"}}, \"adaptive_fix_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.6432, \"eval_loss_holdout\": 2.8704, \"eval_loss\": 2.8704, \"eval_holdout_tokens\": 4077068, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.643/4077068\", \"train_loss_weighted\": 7.517, \"train_runtime_s\": 10347, \"total_steps\": 6103, \"epoch\": 0.26, \"b_star_mean\": 1.431, \"b_star_median\": 0.88, \"b_star_std\": 2.029, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_pct_below_0.5\": 20.9, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_2_to_5\": 6.3, \"b_star_pct_above_5\": 1.9, \"b_star_count\": 25906, \"b_star_p25\": 0.54, \"b_star_p75\": 1.52, \"b_star_pct_above_2\": 16.1, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\"}}, \"adaptive_fix_seed456\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 8.3124, \"train_runtime\": 11436.05, \"train_samples_per_second\": 8.539, \"train_steps_per_second\": 0.534, \"total_steps\": 6103, \"eval_ppl_holdout\": 17.6566, \"eval_loss_holdout\": 2.8711, \"eval_holdout_tokens\": 4077068, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.66/4077068\", \"b_star_count\": 26396, \"b_star_mean\": 1.416, \"b_star_median\": 0.88, \"b_star_std\": 1.993, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.54, \"b_star_p75\": 1.52, \"b_star_pct_below_0.5\": 20.9, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_above_2\": 16.1, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\"}}, \"adaptive_fix_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.5167, \"train_runtime\": 10304.37, \"train_samples_per_second\": 9.476, \"train_steps_per_second\": 0.592, \"total_steps\": 6103, \"eval_ppl_holdout\": 17.6527, \"eval_loss_holdout\": 2.8709, \"eval_holdout_tokens\": 4077068, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.65/4077068\", \"b_star_count\": 26458, \"b_star_mean\": 1.399, \"b_star_median\": 0.871, \"b_star_std\": 1.933, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.54, \"b_star_p75\": 1.512, \"b_star_pct_below_0.5\": 20.9, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_above_2\": 16.1, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\"}}, \"adaptive_v2_seed456\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"adaptive_v2_seed123\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"adaptive_v2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_07_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_06_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_05_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"contamination_60_seed42_r2\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.74, \"eval_loss_holdout\": 2.8759, \"eval_tokens\": 4077068, \"eval_method\": \"sliding_window_2048_stride1024\", \"train_loss\": 9.6349, \"train_runtime_seconds\": 14092.25}, \"conclusion\": \"success\"}, \"contamination_60_grid_b0_5_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl\": 17.704, \"eval_loss\": 2.8738, \"eval_tokens\": 4077068, \"eval_docs\": 5000}}, \"contamination_60_uniform_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.766, \"eval_loss_holdout\": 2.8773, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py sliding-window (stride=1024, max_length=2048, fp16) on data/human/eval_holdout.jsonl\", \"train_loss\": 7.649, \"train_runtime_seconds\": 12904}}, \"bs8_nmin2_seed42_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.8752, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\", \"train_loss\": 5.4065, \"train_steps\": 6103, \"train_runtime_seconds\": 14621.6}}, \"grid_b_low_serial_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"grid_b_low_seed42_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b_low_seed42_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"baseline_qwen3_0.6b\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 22.97, \"eval_loss\": 3.134, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16\"}}, \"contamination_60_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"nmin4_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.6947, \"eval_loss\": 2.8733, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"train_loss\": 7.989, \"total_steps\": 6103, \"train_runtime_s\": 16231, \"train_samples_per_second\": 6.016, \"b_star_count\": 24412, \"b_star_mean\": 0, \"b_star_median\": 0, \"b_star_std\": 0, \"b_star_min\": 0, \"b_star_max\": 0, \"b_star_pct_zero\": 100, \"ess_mean\": 4, \"ess_min\": 4, \"ess_max\": 4}, \"conclusion\": \"success\"}, \"bs8_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bs8_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"tau_09_seed42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_ppl_holdout\": 17.712, \"eval_loss\": 2.8742, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 2.36, \"b_star_median\": 1.32, \"b_star_std\": 3.04, \"b_star_pct_above_2\": 33.7}}, \"tau_07_seed42\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.6707, \"total_steps\": 6103, \"train_runtime_s\": 15065, \"train_samples_per_second\": 6.482, \"eval_ppl_holdout\": 17.6793, \"eval_loss\": 2.8724, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 0.8943, \"b_star_median\": 0.58, \"b_star_std\": 1.4007, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.3306, \"b_star_p75\": 0.9712, \"b_star_pct_zero\": 5.8, \"b_star_pct_below_0.5\": 36, \"b_star_pct_0.5_to_1\": 34.2, \"b_star_pct_1_to_2\": 16.2, \"b_star_pct_above_2\": 7.7}, \"conclusion\": \"success\"}, \"tau_06_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.6805, \"eval_loss\": 2.8725, \"train_loss\": 9.275, \"total_steps\": 6103, \"train_runtime_s\": 13436.64, \"train_samples_per_second\": 7.267, \"b_star_mean\": 0.5899, \"b_star_median\": 0.3746, \"b_star_std\": 1.0693, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.1195, \"b_star_p75\": 0.66, \"b_star_zero_frac\": 0.156, \"b_star_nonzero_mean\": 0.699, \"b_star_nonzero_median\": 0.4473}, \"conclusion\": \"success\"}, \"tau_05_seed42\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 8.849, \"total_steps\": 6103, \"epoch\": 0.26, \"train_runtime_s\": 13431.4, \"train_samples_per_second\": 7.27, \"eval_ppl_holdout\": 17.688, \"eval_loss\": 2.8729, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 0.3923, \"b_star_median\": 0.1707, \"b_star_std\": 0.8821, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0, \"b_star_p75\": 0.4366, \"b_star_pct_zero\": 29.1, \"b_star_pct_below_0.5\": 78.4, \"b_star_pct_0.5_to_1\": 12.9, \"b_star_pct_1_to_2\": 5.7, \"b_star_pct_above_2\": 2.9}, \"conclusion\": \"success\"}, \"adaptive_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.2354, \"train_runtime_s\": 13130.09, \"total_steps\": 6103, \"train_samples_per_second\": 7.437, \"train_steps_per_second\": 0.465, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.09-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.6419, \"eval_loss_holdout\": 2.8703, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.64/4080000 from inline eval\"}, \"conclusion\": \"success\"}, \"adaptive_seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.2665, \"train_runtime_s\": 13197.18, \"total_steps\": 6103, \"train_samples_per_second\": 7.399, \"train_steps_per_second\": 0.462, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.04-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.6308, \"eval_loss_holdout\": 2.8696, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.63/4080000 from inline eval\"}, \"conclusion\": \"success\"}, \"adaptive_seed42\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.2665, \"train_runtime_s\": 13115.09, \"total_steps\": 6103, \"train_samples_per_second\": 7.445, \"train_steps_per_second\": 0.465, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.03-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.644, \"eval_loss_holdout\": 2.8704, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; confirmed unchanged from prior post-hoc (was 17.644/4077068)\"}, \"conclusion\": \"success\"}, \"uniform_seed456\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.2895, \"total_steps\": 6103, \"train_duration_s\": 11974, \"eval_ppl_holdout\": 17.7015, \"eval_loss_holdout\": 2.8737, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.70/4080000 from inline eval\"}}, \"uniform_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.3121, \"total_steps\": 6103, \"train_duration_s\": 11994, \"eval_ppl_holdout\": 17.6861, \"eval_loss_holdout\": 2.8728, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\"}}, \"uniform_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.3104, \"total_steps\": 6103, \"train_duration_s\": 11946, \"eval_ppl_holdout\": 17.6939, \"eval_loss_holdout\": 2.8732, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\"}}, \"detector_modernbert\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"nmin1_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.789, \"eval_loss\": 2.8786, \"eval_holdout_tokens\": 4077068, \"b_star_mean\": 7.197, \"b_star_median\": 1.746, \"b_star_std\": 8.374, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.803, \"b_star_p75\": 20, \"b_star_zero_frac\": 0.019, \"b_star_pct_below_0.5\": 13.1, \"b_star_pct_0.5_to_1\": 19.1, \"b_star_pct_1_to_2\": 21.1, \"b_star_pct_above_2\": 46.7, \"b_star_count\": 24412, \"alpha_eff_mean\": 0.714, \"alpha_eff_median\": 0.8}, \"conclusion\": \"success\"}, \"golden_ratio_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.654, \"eval_loss\": 2.871, \"train_loss\": 2.1145, \"train_loss_last500\": 2.109, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_runtime_s\": 13442, \"gpu_hours\": 3.73}, \"conclusion\": \"success\"}, \"tau_0.6_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"grid_b_low_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b1_5_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.435, \"total_steps\": 6103, \"train_runtime_s\": 12950.16, \"gpu_hours\": 3.67, \"train_samples_per_second\": 7.54, \"eval_loss\": 2.8741, \"eval_ppl_holdout\": 17.71, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.875, \"eval_tokens\": 5004058}, \"conclusion\": \"success\"}, \"grid_b1_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.178, \"total_steps\": 6103, \"train_runtime_s\": 12963.87, \"gpu_hours\": 3.67, \"train_samples_per_second\": 7.532, \"eval_loss\": 2.8725, \"eval_ppl_holdout\": 17.68, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.8734, \"eval_tokens\": 5004058}, \"conclusion\": \"success\"}, \"grid_b0_5_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.5622, \"total_steps\": 6103, \"train_runtime_s\": 12953.96, \"gpu_hours\": 3.6, \"train_samples_per_second\": 7.538, \"eval_loss\": 2.8705, \"eval_ppl_holdout\": 17.65, \"eval_holdout_tokens\": 4077068}, \"conclusion\": \"success\"}, \"grid_b_seed42_batch\": {\"status\": \"DONE\", \"metrics\": {\"b_values\": [0.5, 1, 1.5, 2, 3, 5], \"b0_5_train_loss\": 9.598, \"b0_5_completed\": true, \"b1_0_completed\": true, \"b1_5_completed\": true, \"b2_0_current_step\": 5149, \"b2_0_total_steps\": 6103, \"completed_b_values\": [0.5, 1, 1.5, 2, 3], \"current_b\": 5, \"total_steps\": 6103, \"current_step\": 3422, \"b5_0_progress_pct\": 56, \"eta_minutes\": 95, \"b2_0_completed\": true, \"b2_0_train_loss\": 10.621, \"b2_0_train_runtime_s\": 13034, \"b3_0_completed\": true, \"b3_0_train_loss\": 10.754, \"b3_0_train_runtime_s\": 13036, \"all_completed\": true, \"b1_0_train_loss\": 10.223, \"b1_5_train_loss\": 10.485, \"b5_0_train_loss\": 10.858, \"b0_5_runtime_s\": 13036, \"b1_0_runtime_s\": 12968, \"b1_5_runtime_s\": 14789, \"b2_0_runtime_s\": 13034, \"b3_0_runtime_s\": 13036, \"b5_0_runtime_s\": 13115, \"note\": \"eval_ppl missing - no --eval_data_path in batch script, post-hoc eval pending\", \"b0_5_eval_ppl\": 17.651, \"b1_0_eval_ppl\": 17.692, \"b1_5_eval_ppl\": 17.718, \"b2_0_eval_ppl\": 17.741, \"b3_0_eval_ppl\": 17.774, \"b5_0_eval_ppl\": 17.818, \"eval_holdout_tokens\": 4077068, \"best_b\": 0.5, \"best_eval_ppl\": 17.651}, \"conclusion\": \"success\"}, \"diagnostic_contamination100\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"detector_tfidf_lr\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"auc\": 0.939, \"accuracy\": 0.858, \"ece_raw\": 0.24, \"ece_calibrated\": 0.048, \"temperature_T\": 0.204, \"q_score_mean\": 0.6, \"q_score_std\": 0.374, \"q_score_median\": 0.707, \"mid_range_ratio\": 0.463}}}, \"count\": 88, \"total\": 88, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3636}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "2beef6af-501f-49fc-b9da-d15be8c414f6",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"batchsize16_nmin8_r2\\\": {\\\"status\\\": \\\"QUEUED\\\"}, \\\"rho02_adaptive_tau09_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"random_reweight_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"batch_adaptive_tau_rho06_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"bs8_auto_nmin_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"batchsize16_nmin8_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"rho02_adaptive_tau09_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"batch_adaptive_tau_rho06_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"bs8_auto_nmin_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"grid_b0_3_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"grid_b0_3_seed456\\\": {\\\"status\\\": \\\"ALLOCATED\\\"}, \\\"random_reweight_v2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.83, \\\"eval_loss_holdout\\\": 2.8809}}, \\\"tau_095_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.723, \\\"eval_loss\\\": 2.8749, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\\\", \\\"train_loss\\\": 10.198, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 13699, \\\"train_samples_per_second\\\": 7.128, \\\"b_star_count\\\": 24412, \\\"b_star_mean\\\": 3.0775, \\\"b_star_median\\\": 1.52, \\\"b_star_std\\\": 3.9923, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.8, \\\"b_star_p75\\\": 3.46, \\\"b_star_pct_zero\\\": 0, \\\"b_star_pct_below_0.5\\\": 8.5, \\\"b_star_pct_0.5_to_1\\\": 24.7, \\\"b_star_pct_1_to_2\\\": 26.4, \\\"b_star_pct_above_2\\\": 40.3}, \\\"conclusion\\\": \\\"negative\\\"}, \\\"llama3b_uniform_seed42\\\": {\\\"status\\\": \\\"RUNNING\\\"}, \\\"llama3b_adaptive_seed42\\\": {\\\"status\\\": \\\"RUNNING\\\"}, \\\"hybrid_rho06_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_loss_holdout\\\": 2.8637, \\\"eval_ppl_holdout\\\": 17.53}}, \\\"batch_adaptive_tau_rho04_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"eval_loss_holdout\\\": 2.8725, \\\"eval_ppl_holdout\\\": 17.681, \\\"train_loss\\\": 9.8206, \\\"train_runtime_sec\\\": 45402.86}}, \\\"p0_contamination_60_datagen\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"total_lines\\\": 371499, \\\"synthetic_count\\\": 222900, \\\"human_count\\\": 148599, \\\"actual_contamination_ratio\\\": 0.6, \\\"q_score_mean\\\": 0.6243, \\\"q_score_std\\\": 0.3703, \\\"q_score_median\\\": 0.7753, \\\"file_size_mb\\\": 907}}, \\\"datagen_synthetic_4gpu\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b5_0_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 10.8468, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 14434, \\\"gpu_hours\\\": 4.01, \\\"eval_ppl_holdout\\\": 17.8039, \\\"eval_loss\\\": 2.8794, \\\"eval_holdout_tokens\\\": 4077068}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b3_0_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 10.7422, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 12955.83, \\\"gpu_hours\\\": 3.6, \\\"eval_ppl_holdout\\\": 17.76, \\\"eval_loss\\\": 2.877, \\\"eval_holdout_tokens\\\": 4077068}}, \\\"grid_b2_0_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 10.61, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 13058.8, \\\"gpu_hours\\\": 3.63, \\\"train_samples_per_second\\\": 7.478, \\\"train_steps_per_second\\\": 0.467, \\\"eval_ppl_holdout\\\": 17.725, \\\"eval_loss\\\": 2.875, \\\"eval_holdout_tokens\\\": 4077068}}, \\\"grid_b1_5_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 10.4776, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 15053.1, \\\"gpu_hours\\\": 4.18, \\\"eval_ppl_holdout\\\": 17.701, \\\"eval_loss\\\": 2.8736}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b1_0_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.674, \\\"eval_loss\\\": 2.8721, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 10.218, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 13878, \\\"gpu_hours\\\": 3.88}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b0_5_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.638, \\\"eval_loss\\\": 2.87, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 9.601, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 13104, \\\"gpu_hours\\\": 3.8}, \\\"conclusion\\\": \\\"success\\\"}, \\\"ess_only_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.72, \\\"eval_loss_holdout\\\": 2.8746, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\\\", \\\"eval_note\\\": \\\"Also ran on scored_data.jsonl (train data): ppl=9.66, loss=2.2677, tokens=3029693\\\", \\\"train_loss\\\": 10.2159, \\\"train_steps\\\": 6103, \\\"train_runtime_seconds\\\": 12959.5, \\\"b_star_mean\\\": 3.55, \\\"b_star_median\\\": 1.5918, \\\"b_star_std\\\": 4.7209, \\\"b_star_min\\\": 0.2344, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.8398, \\\"b_star_p75\\\": 3.8281, \\\"b_star_p90\\\": 9.5996, \\\"b_star_count\\\": 21971, \\\"vs_uniform_ppl_delta\\\": \\\"+0.034\\\", \\\"vs_adaptive_fix_ppl_delta\\\": \\\"+0.077\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"hybrid_rho04_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_loss_holdout\\\": 2.863, \\\"eval_ppl_holdout\\\": 17.514}}, \\\"grid_b0_2_seed42\\\": {\\\"status\\\": \\\"RUNNING\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"threshold_q03_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_loss_holdout\\\": 2.848, \\\"eval_ppl_holdout\\\": 17.253}}, \\\"rho02_uniform_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.336, \\\"eval_loss_holdout\\\": 2.853, \\\"eval_holdout_tokens\\\": 4077068}}, \\\"threshold_q07_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"random_reweight_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"grid_b0_1_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.657, \\\"eval_loss_holdout\\\": 2.871}, \\\"conclusion\\\": \\\"success\\\"}, \\\"contamination_60_tau06_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.7359, \\\"eval_loss_holdout\\\": 2.8756, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 8.9804, \\\"train_runtime_seconds\\\": 13367.3, \\\"train_samples_per_second\\\": 7.305, \\\"total_steps\\\": 6103, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"contamination_60_tau07_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.73, \\\"eval_loss_holdout\\\": 2.875, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 9.358, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"detect_remove_baseline_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.29, \\\"eval_loss_holdout\\\": 2.8499, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 11.003, \\\"train_runtime_seconds\\\": 13248, \\\"total_steps\\\": 6103, \\\"train_samples_per_second\\\": 7.371}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b0_3_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.64, \\\"eval_loss_holdout\\\": 2.8702, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"train_loss\\\": 9.1154, \\\"train_runtime_seconds\\\": 13365.79, \\\"train_samples_per_second\\\": 7.306, \\\"total_steps\\\": 6103, \\\"b_fixed\\\": 0.3, \\\"alpha_eff_typical_range\\\": \\\"0.07-0.88\\\", \\\"ess_typical_range\\\": \\\"2.3-4.0\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"contamination_60_ess_only_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.77, \\\"eval_loss_holdout\\\": 2.8775, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 9.842, \\\"total_steps\\\": 6103, \\\"train_runtime_seconds\\\": 13152}, \\\"conclusion\\\": \\\"success\\\"}, \\\"tau_095_nmin2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"tau_09_nmin2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"nmin5_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"grid_b5_0_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.993, \\\"eval_loss\\\": 2.89, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 5.488, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 6601, \\\"gpu_hours\\\": 1.83, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b3_0_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.921, \\\"eval_loss\\\": 2.886, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 5.435, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 6602, \\\"gpu_hours\\\": 1.83, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b2_0_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.989, \\\"eval_loss\\\": 2.8898, \\\"eval_holdout_tokens\\\": 4077068, \\\"train_loss\\\": 10.625, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 12969, \\\"gpu_hours\\\": 3.6, \\\"train_samples_per_second\\\": 7.53, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"ess_only_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl\\\": 17.719, \\\"eval_loss\\\": 2.8746, \\\"eval_tokens\\\": 4077068, \\\"train_loss\\\": 10.174, \\\"vs_uniform_ppl_delta\\\": \\\"+0.018\\\", \\\"vs_adaptive_ppl_delta\\\": \\\"+0.077\\\", \\\"vs_adaptive_fix_ppl_delta\\\": \\\"+0.062\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"ess_only_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl\\\": 17.73, \\\"eval_loss\\\": 2.875, \\\"b_star_median\\\": 1.58, \\\"b_star_mean\\\": 3.51, \\\"vs_uniform_ppl_delta\\\": \\\"+0.038\\\", \\\"vs_adaptive_ppl_delta\\\": \\\"+0.08\\\"}}, \\\"adaptive_fix_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.6432, \\\"eval_loss_holdout\\\": 2.8704, \\\"eval_loss\\\": 2.8704, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.643/4077068\\\", \\\"train_loss_weighted\\\": 7.517, \\\"train_runtime_s\\\": 10347, \\\"total_steps\\\": 6103, \\\"epoch\\\": 0.26, \\\"b_star_mean\\\": 1.431, \\\"b_star_median\\\": 0.88, \\\"b_star_std\\\": 2.029, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_pct_below_0.5\\\": 20.9, \\\"b_star_pct_0.5_to_1\\\": 35.7, \\\"b_star_pct_1_to_2\\\": 27.3, \\\"b_star_pct_2_to_5\\\": 6.3, \\\"b_star_pct_above_5\\\": 1.9, \\\"b_star_count\\\": 25906, \\\"b_star_p25\\\": 0.54, \\\"b_star_p75\\\": 1.52, \\\"b_star_pct_above_2\\\": 16.1, \\\"b_star_note\\\": \\\"Training-only records (eval checkpoint records with b*=0 excluded)\\\"}}, \\\"adaptive_fix_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 8.3124, \\\"train_runtime\\\": 11436.05, \\\"train_samples_per_second\\\": 8.539, \\\"train_steps_per_second\\\": 0.534, \\\"total_steps\\\": 6103, \\\"eval_ppl_holdout\\\": 17.6566, \\\"eval_loss_holdout\\\": 2.8711, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.66/4077068\\\", \\\"b_star_count\\\": 26396, \\\"b_star_mean\\\": 1.416, \\\"b_star_median\\\": 0.88, \\\"b_star_std\\\": 1.993, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.54, \\\"b_star_p75\\\": 1.52, \\\"b_star_pct_below_0.5\\\": 20.9, \\\"b_star_pct_0.5_to_1\\\": 35.7, \\\"b_star_pct_1_to_2\\\": 27.3, \\\"b_star_pct_above_2\\\": 16.1, \\\"b_star_note\\\": \\\"Training-only records (eval checkpoint records with b*=0 excluded)\\\"}}, \\\"adaptive_fix_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 7.5167, \\\"train_runtime\\\": 10304.37, \\\"train_samples_per_second\\\": 9.476, \\\"train_steps_per_second\\\": 0.592, \\\"total_steps\\\": 6103, \\\"eval_ppl_holdout\\\": 17.6527, \\\"eval_loss_holdout\\\": 2.8709, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.65/4077068\\\", \\\"b_star_count\\\": 26458, \\\"b_star_mean\\\": 1.399, \\\"b_star_median\\\": 0.871, \\\"b_star_std\\\": 1.933, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.54, \\\"b_star_p75\\\": 1.512, \\\"b_star_pct_below_0.5\\\": 20.9, \\\"b_star_pct_0.5_to_1\\\": 35.7, \\\"b_star_pct_1_to_2\\\": 27.3, \\\"b_star_pct_above_2\\\": 16.1, \\\"b_star_note\\\": \\\"Training-only records (eval checkpoint records with b*=0 excluded)\\\"}}, \\\"adaptive_v2_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"adaptive_v2_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"adaptive_v2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"tau_07_nmin2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"tau_06_nmin2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"tau_05_nmin2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"contamination_60_seed42_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.74, \\\"eval_loss_holdout\\\": 2.8759, \\\"eval_tokens\\\": 4077068, \\\"eval_method\\\": \\\"sliding_window_2048_stride1024\\\", \\\"train_loss\\\": 9.6349, \\\"train_runtime_seconds\\\": 14092.25}, \\\"conclusion\\\": \\\"success\\\"}, \\\"contamination_60_grid_b0_5_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl\\\": 17.704, \\\"eval_loss\\\": 2.8738, \\\"eval_tokens\\\": 4077068, \\\"eval_docs\\\": 5000}}, \\\"contamination_60_uniform_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.766, \\\"eval_loss_holdout\\\": 2.8773, \\\"eval_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py sliding-window (stride=1024, max_length=2048, fp16) on data/human/eval_holdout.jsonl\\\", \\\"train_loss\\\": 7.649, \\\"train_runtime_seconds\\\": 12904}}, \\\"bs8_nmin2_seed42_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.73, \\\"eval_loss_holdout\\\": 2.8752, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\\\", \\\"train_loss\\\": 5.4065, \\\"train_steps\\\": 6103, \\\"train_runtime_seconds\\\": 14621.6}}, \\\"grid_b_low_serial_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"grid_b_low_seed42_r3\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"grid_b_low_seed42_r2\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"baseline_qwen3_0.6b\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 22.97, \\\"eval_loss\\\": 3.134, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"sliding_window_stride1024_maxlen2048_fp16\\\"}}, \\\"contamination_60_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"nmin4_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.6947, \\\"eval_loss\\\": 2.8733, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\\\", \\\"train_loss\\\": 7.989, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 16231, \\\"train_samples_per_second\\\": 6.016, \\\"b_star_count\\\": 24412, \\\"b_star_mean\\\": 0, \\\"b_star_median\\\": 0, \\\"b_star_std\\\": 0, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 0, \\\"b_star_pct_zero\\\": 100, \\\"ess_mean\\\": 4, \\\"ess_min\\\": 4, \\\"ess_max\\\": 4}, \\\"conclusion\\\": \\\"success\\\"}, \\\"bs8_nmin2_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"bs8_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"tau_09_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.712, \\\"eval_loss\\\": 2.8742, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15\\\", \\\"b_star_count\\\": 24412, \\\"b_star_mean\\\": 2.36, \\\"b_star_median\\\": 1.32, \\\"b_star_std\\\": 3.04, \\\"b_star_pct_above_2\\\": 33.7}}, \\\"tau_07_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 9.6707, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 15065, \\\"train_samples_per_second\\\": 6.482, \\\"eval_ppl_holdout\\\": 17.6793, \\\"eval_loss\\\": 2.8724, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15\\\", \\\"b_star_count\\\": 24412, \\\"b_star_mean\\\": 0.8943, \\\"b_star_median\\\": 0.58, \\\"b_star_std\\\": 1.4007, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.3306, \\\"b_star_p75\\\": 0.9712, \\\"b_star_pct_zero\\\": 5.8, \\\"b_star_pct_below_0.5\\\": 36, \\\"b_star_pct_0.5_to_1\\\": 34.2, \\\"b_star_pct_1_to_2\\\": 16.2, \\\"b_star_pct_above_2\\\": 7.7}, \\\"conclusion\\\": \\\"success\\\"}, \\\"tau_06_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.6805, \\\"eval_loss\\\": 2.8725, \\\"train_loss\\\": 9.275, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 13436.64, \\\"train_samples_per_second\\\": 7.267, \\\"b_star_mean\\\": 0.5899, \\\"b_star_median\\\": 0.3746, \\\"b_star_std\\\": 1.0693, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.1195, \\\"b_star_p75\\\": 0.66, \\\"b_star_zero_frac\\\": 0.156, \\\"b_star_nonzero_mean\\\": 0.699, \\\"b_star_nonzero_median\\\": 0.4473}, \\\"conclusion\\\": \\\"success\\\"}, \\\"tau_05_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 8.849, \\\"total_steps\\\": 6103, \\\"epoch\\\": 0.26, \\\"train_runtime_s\\\": 13431.4, \\\"train_samples_per_second\\\": 7.27, \\\"eval_ppl_holdout\\\": 17.688, \\\"eval_loss\\\": 2.8729, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15\\\", \\\"b_star_count\\\": 24412, \\\"b_star_mean\\\": 0.3923, \\\"b_star_median\\\": 0.1707, \\\"b_star_std\\\": 0.8821, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0, \\\"b_star_p75\\\": 0.4366, \\\"b_star_pct_zero\\\": 29.1, \\\"b_star_pct_below_0.5\\\": 78.4, \\\"b_star_pct_0.5_to_1\\\": 12.9, \\\"b_star_pct_1_to_2\\\": 5.7, \\\"b_star_pct_above_2\\\": 2.9}, \\\"conclusion\\\": \\\"success\\\"}, \\\"adaptive_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 9.2354, \\\"train_runtime_s\\\": 13130.09, \\\"total_steps\\\": 6103, \\\"train_samples_per_second\\\": 7.437, \\\"train_steps_per_second\\\": 0.465, \\\"epoch\\\": 0.26, \\\"weighting_method\\\": \\\"adaptive\\\", \\\"tau\\\": 0.8, \\\"n_min\\\": 3, \\\"contamination_ratio\\\": 0.4, \\\"b_star\\\": \\\"per-batch adaptive (0.0-3.8)\\\", \\\"alpha_eff_range\\\": \\\"0.09-0.80 (capped at tau)\\\", \\\"eval_ppl_holdout\\\": 17.6419, \\\"eval_loss_holdout\\\": 2.8703, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.64/4080000 from inline eval\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"adaptive_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 9.2665, \\\"train_runtime_s\\\": 13197.18, \\\"total_steps\\\": 6103, \\\"train_samples_per_second\\\": 7.399, \\\"train_steps_per_second\\\": 0.462, \\\"epoch\\\": 0.26, \\\"weighting_method\\\": \\\"adaptive\\\", \\\"tau\\\": 0.8, \\\"n_min\\\": 3, \\\"contamination_ratio\\\": 0.4, \\\"b_star\\\": \\\"per-batch adaptive (0.0-3.8)\\\", \\\"alpha_eff_range\\\": \\\"0.04-0.80 (capped at tau)\\\", \\\"eval_ppl_holdout\\\": 17.6308, \\\"eval_loss_holdout\\\": 2.8696, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.63/4080000 from inline eval\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"adaptive_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 9.2665, \\\"train_runtime_s\\\": 13115.09, \\\"total_steps\\\": 6103, \\\"train_samples_per_second\\\": 7.445, \\\"train_steps_per_second\\\": 0.465, \\\"epoch\\\": 0.26, \\\"weighting_method\\\": \\\"adaptive\\\", \\\"tau\\\": 0.8, \\\"n_min\\\": 3, \\\"contamination_ratio\\\": 0.4, \\\"b_star\\\": \\\"per-batch adaptive (0.0-3.8)\\\", \\\"alpha_eff_range\\\": \\\"0.03-0.80 (capped at tau)\\\", \\\"eval_ppl_holdout\\\": 17.644, \\\"eval_loss_holdout\\\": 2.8704, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; confirmed unchanged from prior post-hoc (was 17.644/4077068)\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"uniform_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 7.2895, \\\"total_steps\\\": 6103, \\\"train_duration_s\\\": 11974, \\\"eval_ppl_holdout\\\": 17.7015, \\\"eval_loss_holdout\\\": 2.8737, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.70/4080000 from inline eval\\\"}}, \\\"uniform_seed123\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 7.3121, \\\"total_steps\\\": 6103, \\\"train_duration_s\\\": 11994, \\\"eval_ppl_holdout\\\": 17.6861, \\\"eval_loss_holdout\\\": 2.8728, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\\\"}}, \\\"uniform_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 7.3104, \\\"total_steps\\\": 6103, \\\"train_duration_s\\\": 11946, \\\"eval_ppl_holdout\\\": 17.6939, \\\"eval_loss_holdout\\\": 2.8732, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_method\\\": \\\"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\\\", \\\"eval_note\\\": \\\"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\\\"}}, \\\"detector_modernbert\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"nmin1_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.789, \\\"eval_loss\\\": 2.8786, \\\"eval_holdout_tokens\\\": 4077068, \\\"b_star_mean\\\": 7.197, \\\"b_star_median\\\": 1.746, \\\"b_star_std\\\": 8.374, \\\"b_star_min\\\": 0, \\\"b_star_max\\\": 20, \\\"b_star_p25\\\": 0.803, \\\"b_star_p75\\\": 20, \\\"b_star_zero_frac\\\": 0.019, \\\"b_star_pct_below_0.5\\\": 13.1, \\\"b_star_pct_0.5_to_1\\\": 19.1, \\\"b_star_pct_1_to_2\\\": 21.1, \\\"b_star_pct_above_2\\\": 46.7, \\\"b_star_count\\\": 24412, \\\"alpha_eff_mean\\\": 0.714, \\\"alpha_eff_median\\\": 0.8}, \\\"conclusion\\\": \\\"success\\\"}, \\\"golden_ratio_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"eval_ppl_holdout\\\": 17.654, \\\"eval_loss\\\": 2.871, \\\"train_loss\\\": 2.1145, \\\"train_loss_last500\\\": 2.109, \\\"eval_holdout_tokens\\\": 4077068, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 13442, \\\"gpu_hours\\\": 3.73}, \\\"conclusion\\\": \\\"success\\\"}, \\\"tau_0.6_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"grid_b_low_seed42\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"failed\\\"}, \\\"grid_b1_5_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 10.435, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 12950.16, \\\"gpu_hours\\\": 3.67, \\\"train_samples_per_second\\\": 7.54, \\\"eval_loss\\\": 2.8741, \\\"eval_ppl_holdout\\\": 17.71, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_loss_holdout\\\": 2.875, \\\"eval_tokens\\\": 5004058}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b1_0_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 10.178, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 12963.87, \\\"gpu_hours\\\": 3.67, \\\"train_samples_per_second\\\": 7.532, \\\"eval_loss\\\": 2.8725, \\\"eval_ppl_holdout\\\": 17.68, \\\"eval_holdout_tokens\\\": 4077068, \\\"eval_loss_holdout\\\": 2.8734, \\\"eval_tokens\\\": 5004058}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b0_5_seed456\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"train_loss\\\": 9.5622, \\\"total_steps\\\": 6103, \\\"train_runtime_s\\\": 12953.96, \\\"gpu_hours\\\": 3.6, \\\"train_samples_per_second\\\": 7.538, \\\"eval_loss\\\": 2.8705, \\\"eval_ppl_holdout\\\": 17.65, \\\"eval_holdout_tokens\\\": 4077068}, \\\"conclusion\\\": \\\"success\\\"}, \\\"grid_b_seed42_batch\\\": {\\\"status\\\": \\\"DONE\\\", \\\"metrics\\\": {\\\"b_values\\\": [0.5, 1, 1.5, 2, 3, 5], \\\"b0_5_train_loss\\\": 9.598, \\\"b0_5_completed\\\": true, \\\"b1_0_completed\\\": true, \\\"b1_5_completed\\\": true, \\\"b2_0_current_step\\\": 5149, \\\"b2_0_total_steps\\\": 6103, \\\"completed_b_values\\\": [0.5, 1, 1.5, 2, 3], \\\"current_b\\\": 5, \\\"total_steps\\\": 6103, \\\"current_step\\\": 3422, \\\"b5_0_progress_pct\\\": 56, \\\"eta_minutes\\\": 95, \\\"b2_0_completed\\\": true, \\\"b2_0_train_loss\\\": 10.621, \\\"b2_0_train_runtime_s\\\": 13034, \\\"b3_0_completed\\\": true, \\\"b3_0_train_loss\\\": 10.754, \\\"b3_0_train_runtime_s\\\": 13036, \\\"all_completed\\\": true, \\\"b1_0_train_loss\\\": 10.223, \\\"b1_5_train_loss\\\": 10.485, \\\"b5_0_train_loss\\\": 10.858, \\\"b0_5_runtime_s\\\": 13036, \\\"b1_0_runtime_s\\\": 12968, \\\"b1_5_runtime_s\\\": 14789, \\\"b2_0_runtime_s\\\": 13034, \\\"b3_0_runtime_s\\\": 13036, \\\"b5_0_runtime_s\\\": 13115, \\\"note\\\": \\\"eval_ppl missing - no --eval_data_path in batch script, post-hoc eval pending\\\", \\\"b0_5_eval_ppl\\\": 17.651, \\\"b1_0_eval_ppl\\\": 17.692, \\\"b1_5_eval_ppl\\\": 17.718, \\\"b2_0_eval_ppl\\\": 17.741, \\\"b3_0_eval_ppl\\\": 17.774, \\\"b5_0_eval_ppl\\\": 17.818, \\\"eval_holdout_tokens\\\": 4077068, \\\"best_b\\\": 0.5, \\\"best_eval_ppl\\\": 17.651}, \\\"conclusion\\\": \\\"success\\\"}, \\\"diagnostic_contamination100\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, \\\"detector_tfidf_lr\\\": {\\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"auc\\\": 0.939, \\\"accuracy\\\": 0.858, \\\"ece_raw\\\": 0.24, \\\"ece_calibrated\\\": 0.048, \\\"temperature_T\\\": 0.204, \\\"q_score_mean\\\": 0.6, \\\"q_score_std\\\": 0.374, \\\"q_score_median\\\": 0.707, \\\"mid_range_ratio\\\": 0.463}}}, \\\"count\\\": 88, \\\"total\\\": 88, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.3636}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"batchsize16_nmin8_r2\": {\"status\": \"QUEUED\"}, \"rho02_adaptive_tau09_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"random_reweight_seed123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"batch_adaptive_tau_rho06_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bs8_auto_nmin_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"batchsize16_nmin8_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rho02_adaptive_tau09_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"batch_adaptive_tau_rho06_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bs8_auto_nmin_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b0_3_seed123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b0_3_seed456\": {\"status\": \"ALLOCATED\"}, \"random_reweight_v2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.83, \"eval_loss_holdout\": 2.8809}}, \"tau_095_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.723, \"eval_loss\": 2.8749, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"train_loss\": 10.198, \"total_steps\": 6103, \"train_runtime_s\": 13699, \"train_samples_per_second\": 7.128, \"b_star_count\": 24412, \"b_star_mean\": 3.0775, \"b_star_median\": 1.52, \"b_star_std\": 3.9923, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.8, \"b_star_p75\": 3.46, \"b_star_pct_zero\": 0, \"b_star_pct_below_0.5\": 8.5, \"b_star_pct_0.5_to_1\": 24.7, \"b_star_pct_1_to_2\": 26.4, \"b_star_pct_above_2\": 40.3}, \"conclusion\": \"negative\"}, \"llama3b_uniform_seed42\": {\"status\": \"RUNNING\"}, \"llama3b_adaptive_seed42\": {\"status\": \"RUNNING\"}, \"hybrid_rho06_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss_holdout\": 2.8637, \"eval_ppl_holdout\": 17.53}}, \"batch_adaptive_tau_rho04_seed42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_loss_holdout\": 2.8725, \"eval_ppl_holdout\": 17.681, \"train_loss\": 9.8206, \"train_runtime_sec\": 45402.86}}, \"p0_contamination_60_datagen\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_lines\": 371499, \"synthetic_count\": 222900, \"human_count\": 148599, \"actual_contamination_ratio\": 0.6, \"q_score_mean\": 0.6243, \"q_score_std\": 0.3703, \"q_score_median\": 0.7753, \"file_size_mb\": 907}}, \"datagen_synthetic_4gpu\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"grid_b5_0_seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.8468, \"total_steps\": 6103, \"train_runtime_s\": 14434, \"gpu_hours\": 4.01, \"eval_ppl_holdout\": 17.8039, \"eval_loss\": 2.8794, \"eval_holdout_tokens\": 4077068}, \"conclusion\": \"success\"}, \"grid_b3_0_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 10.7422, \"total_steps\": 6103, \"train_runtime_s\": 12955.83, \"gpu_hours\": 3.6, \"eval_ppl_holdout\": 17.76, \"eval_loss\": 2.877, \"eval_holdout_tokens\": 4077068}}, \"grid_b2_0_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 10.61, \"total_steps\": 6103, \"train_runtime_s\": 13058.8, \"gpu_hours\": 3.63, \"train_samples_per_second\": 7.478, \"train_steps_per_second\": 0.467, \"eval_ppl_holdout\": 17.725, \"eval_loss\": 2.875, \"eval_holdout_tokens\": 4077068}}, \"grid_b1_5_seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.4776, \"total_steps\": 6103, \"train_runtime_s\": 15053.1, \"gpu_hours\": 4.18, \"eval_ppl_holdout\": 17.701, \"eval_loss\": 2.8736}, \"conclusion\": \"success\"}, \"grid_b1_0_seed123\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.674, \"eval_loss\": 2.8721, \"eval_holdout_tokens\": 4077068, \"train_loss\": 10.218, \"total_steps\": 6103, \"train_runtime_s\": 13878, \"gpu_hours\": 3.88}, \"conclusion\": \"success\"}, \"grid_b0_5_seed123\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.638, \"eval_loss\": 2.87, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.601, \"total_steps\": 6103, \"train_runtime_s\": 13104, \"gpu_hours\": 3.8}, \"conclusion\": \"success\"}, \"ess_only_seed123\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.72, \"eval_loss_holdout\": 2.8746, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\", \"eval_note\": \"Also ran on scored_data.jsonl (train data): ppl=9.66, loss=2.2677, tokens=3029693\", \"train_loss\": 10.2159, \"train_steps\": 6103, \"train_runtime_seconds\": 12959.5, \"b_star_mean\": 3.55, \"b_star_median\": 1.5918, \"b_star_std\": 4.7209, \"b_star_min\": 0.2344, \"b_star_max\": 20, \"b_star_p25\": 0.8398, \"b_star_p75\": 3.8281, \"b_star_p90\": 9.5996, \"b_star_count\": 21971, \"vs_uniform_ppl_delta\": \"+0.034\", \"vs_adaptive_fix_ppl_delta\": \"+0.077\"}, \"conclusion\": \"success\"}, \"hybrid_rho04_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss_holdout\": 2.863, \"eval_ppl_holdout\": 17.514}}, \"grid_b0_2_seed42\": {\"status\": \"RUNNING\", \"conclusion\": \"killed\"}, \"threshold_q03_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss_holdout\": 2.848, \"eval_ppl_holdout\": 17.253}}, \"rho02_uniform_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.336, \"eval_loss_holdout\": 2.853, \"eval_holdout_tokens\": 4077068}}, \"threshold_q07_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"random_reweight_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b0_1_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.657, \"eval_loss_holdout\": 2.871}, \"conclusion\": \"success\"}, \"contamination_60_tau06_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.7359, \"eval_loss_holdout\": 2.8756, \"eval_holdout_tokens\": 4077068, \"train_loss\": 8.9804, \"train_runtime_seconds\": 13367.3, \"train_samples_per_second\": 7.305, \"total_steps\": 6103, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"contamination_60_tau07_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.875, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.358, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"detect_remove_baseline_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.29, \"eval_loss_holdout\": 2.8499, \"eval_holdout_tokens\": 4077068, \"train_loss\": 11.003, \"train_runtime_seconds\": 13248, \"total_steps\": 6103, \"train_samples_per_second\": 7.371}, \"conclusion\": \"success\"}, \"grid_b0_3_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.64, \"eval_loss_holdout\": 2.8702, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"train_loss\": 9.1154, \"train_runtime_seconds\": 13365.79, \"train_samples_per_second\": 7.306, \"total_steps\": 6103, \"b_fixed\": 0.3, \"alpha_eff_typical_range\": \"0.07-0.88\", \"ess_typical_range\": \"2.3-4.0\"}, \"conclusion\": \"success\"}, \"contamination_60_ess_only_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.77, \"eval_loss_holdout\": 2.8775, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.842, \"total_steps\": 6103, \"train_runtime_seconds\": 13152}, \"conclusion\": \"success\"}, \"tau_095_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_09_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"nmin5_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"grid_b5_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.993, \"eval_loss\": 2.89, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.488, \"total_steps\": 6103, \"train_runtime_s\": 6601, \"gpu_hours\": 1.83, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"grid_b3_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.921, \"eval_loss\": 2.886, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.435, \"total_steps\": 6103, \"train_runtime_s\": 6602, \"gpu_hours\": 1.83, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"grid_b2_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.989, \"eval_loss\": 2.8898, \"eval_holdout_tokens\": 4077068, \"train_loss\": 10.625, \"total_steps\": 6103, \"train_runtime_s\": 12969, \"gpu_hours\": 3.6, \"train_samples_per_second\": 7.53, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\"}, \"ess_only_seed456\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl\": 17.719, \"eval_loss\": 2.8746, \"eval_tokens\": 4077068, \"train_loss\": 10.174, \"vs_uniform_ppl_delta\": \"+0.018\", \"vs_adaptive_ppl_delta\": \"+0.077\", \"vs_adaptive_fix_ppl_delta\": \"+0.062\"}, \"conclusion\": \"success\"}, \"ess_only_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl\": 17.73, \"eval_loss\": 2.875, \"b_star_median\": 1.58, \"b_star_mean\": 3.51, \"vs_uniform_ppl_delta\": \"+0.038\", \"vs_adaptive_ppl_delta\": \"+0.08\"}}, \"adaptive_fix_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.6432, \"eval_loss_holdout\": 2.8704, \"eval_loss\": 2.8704, \"eval_holdout_tokens\": 4077068, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.643/4077068\", \"train_loss_weighted\": 7.517, \"train_runtime_s\": 10347, \"total_steps\": 6103, \"epoch\": 0.26, \"b_star_mean\": 1.431, \"b_star_median\": 0.88, \"b_star_std\": 2.029, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_pct_below_0.5\": 20.9, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_2_to_5\": 6.3, \"b_star_pct_above_5\": 1.9, \"b_star_count\": 25906, \"b_star_p25\": 0.54, \"b_star_p75\": 1.52, \"b_star_pct_above_2\": 16.1, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\"}}, \"adaptive_fix_seed456\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 8.3124, \"train_runtime\": 11436.05, \"train_samples_per_second\": 8.539, \"train_steps_per_second\": 0.534, \"total_steps\": 6103, \"eval_ppl_holdout\": 17.6566, \"eval_loss_holdout\": 2.8711, \"eval_holdout_tokens\": 4077068, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.66/4077068\", \"b_star_count\": 26396, \"b_star_mean\": 1.416, \"b_star_median\": 0.88, \"b_star_std\": 1.993, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.54, \"b_star_p75\": 1.52, \"b_star_pct_below_0.5\": 20.9, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_above_2\": 16.1, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\"}}, \"adaptive_fix_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.5167, \"train_runtime\": 10304.37, \"train_samples_per_second\": 9.476, \"train_steps_per_second\": 0.592, \"total_steps\": 6103, \"eval_ppl_holdout\": 17.6527, \"eval_loss_holdout\": 2.8709, \"eval_holdout_tokens\": 4077068, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.65/4077068\", \"b_star_count\": 26458, \"b_star_mean\": 1.399, \"b_star_median\": 0.871, \"b_star_std\": 1.933, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.54, \"b_star_p75\": 1.512, \"b_star_pct_below_0.5\": 20.9, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_above_2\": 16.1, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\"}}, \"adaptive_v2_seed456\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"adaptive_v2_seed123\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"adaptive_v2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_07_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_06_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"tau_05_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"contamination_60_seed42_r2\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.74, \"eval_loss_holdout\": 2.8759, \"eval_tokens\": 4077068, \"eval_method\": \"sliding_window_2048_stride1024\", \"train_loss\": 9.6349, \"train_runtime_seconds\": 14092.25}, \"conclusion\": \"success\"}, \"contamination_60_grid_b0_5_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl\": 17.704, \"eval_loss\": 2.8738, \"eval_tokens\": 4077068, \"eval_docs\": 5000}}, \"contamination_60_uniform_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.766, \"eval_loss_holdout\": 2.8773, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py sliding-window (stride=1024, max_length=2048, fp16) on data/human/eval_holdout.jsonl\", \"train_loss\": 7.649, \"train_runtime_seconds\": 12904}}, \"bs8_nmin2_seed42_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.8752, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\", \"train_loss\": 5.4065, \"train_steps\": 6103, \"train_runtime_seconds\": 14621.6}}, \"grid_b_low_serial_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"grid_b_low_seed42_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b_low_seed42_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"baseline_qwen3_0.6b\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 22.97, \"eval_loss\": 3.134, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16\"}}, \"contamination_60_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"nmin4_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.6947, \"eval_loss\": 2.8733, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"train_loss\": 7.989, \"total_steps\": 6103, \"train_runtime_s\": 16231, \"train_samples_per_second\": 6.016, \"b_star_count\": 24412, \"b_star_mean\": 0, \"b_star_median\": 0, \"b_star_std\": 0, \"b_star_min\": 0, \"b_star_max\": 0, \"b_star_pct_zero\": 100, \"ess_mean\": 4, \"ess_min\": 4, \"ess_max\": 4}, \"conclusion\": \"success\"}, \"bs8_nmin2_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bs8_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"tau_09_seed42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"eval_ppl_holdout\": 17.712, \"eval_loss\": 2.8742, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 2.36, \"b_star_median\": 1.32, \"b_star_std\": 3.04, \"b_star_pct_above_2\": 33.7}}, \"tau_07_seed42\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.6707, \"total_steps\": 6103, \"train_runtime_s\": 15065, \"train_samples_per_second\": 6.482, \"eval_ppl_holdout\": 17.6793, \"eval_loss\": 2.8724, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 0.8943, \"b_star_median\": 0.58, \"b_star_std\": 1.4007, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.3306, \"b_star_p75\": 0.9712, \"b_star_pct_zero\": 5.8, \"b_star_pct_below_0.5\": 36, \"b_star_pct_0.5_to_1\": 34.2, \"b_star_pct_1_to_2\": 16.2, \"b_star_pct_above_2\": 7.7}, \"conclusion\": \"success\"}, \"tau_06_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.6805, \"eval_loss\": 2.8725, \"train_loss\": 9.275, \"total_steps\": 6103, \"train_runtime_s\": 13436.64, \"train_samples_per_second\": 7.267, \"b_star_mean\": 0.5899, \"b_star_median\": 0.3746, \"b_star_std\": 1.0693, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.1195, \"b_star_p75\": 0.66, \"b_star_zero_frac\": 0.156, \"b_star_nonzero_mean\": 0.699, \"b_star_nonzero_median\": 0.4473}, \"conclusion\": \"success\"}, \"tau_05_seed42\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 8.849, \"total_steps\": 6103, \"epoch\": 0.26, \"train_runtime_s\": 13431.4, \"train_samples_per_second\": 7.27, \"eval_ppl_holdout\": 17.688, \"eval_loss\": 2.8729, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 0.3923, \"b_star_median\": 0.1707, \"b_star_std\": 0.8821, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0, \"b_star_p75\": 0.4366, \"b_star_pct_zero\": 29.1, \"b_star_pct_below_0.5\": 78.4, \"b_star_pct_0.5_to_1\": 12.9, \"b_star_pct_1_to_2\": 5.7, \"b_star_pct_above_2\": 2.9}, \"conclusion\": \"success\"}, \"adaptive_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.2354, \"train_runtime_s\": 13130.09, \"total_steps\": 6103, \"train_samples_per_second\": 7.437, \"train_steps_per_second\": 0.465, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.09-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.6419, \"eval_loss_holdout\": 2.8703, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.64/4080000 from inline eval\"}, \"conclusion\": \"success\"}, \"adaptive_seed123\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.2665, \"train_runtime_s\": 13197.18, \"total_steps\": 6103, \"train_samples_per_second\": 7.399, \"train_steps_per_second\": 0.462, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.04-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.6308, \"eval_loss_holdout\": 2.8696, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.63/4080000 from inline eval\"}, \"conclusion\": \"success\"}, \"adaptive_seed42\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.2665, \"train_runtime_s\": 13115.09, \"total_steps\": 6103, \"train_samples_per_second\": 7.445, \"train_steps_per_second\": 0.465, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.03-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.644, \"eval_loss_holdout\": 2.8704, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; confirmed unchanged from prior post-hoc (was 17.644/4077068)\"}, \"conclusion\": \"success\"}, \"uniform_seed456\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.2895, \"total_steps\": 6103, \"train_duration_s\": 11974, \"eval_ppl_holdout\": 17.7015, \"eval_loss_holdout\": 2.8737, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.70/4080000 from inline eval\"}}, \"uniform_seed123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.3121, \"total_steps\": 6103, \"train_duration_s\": 11994, \"eval_ppl_holdout\": 17.6861, \"eval_loss_holdout\": 2.8728, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\"}}, \"uniform_seed42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.3104, \"total_steps\": 6103, \"train_duration_s\": 11946, \"eval_ppl_holdout\": 17.6939, \"eval_loss_holdout\": 2.8732, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\"}}, \"detector_modernbert\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"nmin1_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.789, \"eval_loss\": 2.8786, \"eval_holdout_tokens\": 4077068, \"b_star_mean\": 7.197, \"b_star_median\": 1.746, \"b_star_std\": 8.374, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.803, \"b_star_p75\": 20, \"b_star_zero_frac\": 0.019, \"b_star_pct_below_0.5\": 13.1, \"b_star_pct_0.5_to_1\": 19.1, \"b_star_pct_1_to_2\": 21.1, \"b_star_pct_above_2\": 46.7, \"b_star_count\": 24412, \"alpha_eff_mean\": 0.714, \"alpha_eff_median\": 0.8}, \"conclusion\": \"success\"}, \"golden_ratio_seed42\": {\"status\": \"DONE\", \"metrics\": {\"eval_ppl_holdout\": 17.654, \"eval_loss\": 2.871, \"train_loss\": 2.1145, \"train_loss_last500\": 2.109, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_runtime_s\": 13442, \"gpu_hours\": 3.73}, \"conclusion\": \"success\"}, \"tau_0.6_seed42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"grid_b_low_seed42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"grid_b1_5_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.435, \"total_steps\": 6103, \"train_runtime_s\": 12950.16, \"gpu_hours\": 3.67, \"train_samples_per_second\": 7.54, \"eval_loss\": 2.8741, \"eval_ppl_holdout\": 17.71, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.875, \"eval_tokens\": 5004058}, \"conclusion\": \"success\"}, \"grid_b1_0_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 10.178, \"total_steps\": 6103, \"train_runtime_s\": 12963.87, \"gpu_hours\": 3.67, \"train_samples_per_second\": 7.532, \"eval_loss\": 2.8725, \"eval_ppl_holdout\": 17.68, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.8734, \"eval_tokens\": 5004058}, \"conclusion\": \"success\"}, \"grid_b0_5_seed456\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 9.5622, \"total_steps\": 6103, \"train_runtime_s\": 12953.96, \"gpu_hours\": 3.6, \"train_samples_per_second\": 7.538, \"eval_loss\": 2.8705, \"eval_ppl_holdout\": 17.65, \"eval_holdout_tokens\": 4077068}, \"conclusion\": \"success\"}, \"grid_b_seed42_batch\": {\"status\": \"DONE\", \"metrics\": {\"b_values\": [0.5, 1, 1.5, 2, 3, 5], \"b0_5_train_loss\": 9.598, \"b0_5_completed\": true, \"b1_0_completed\": true, \"b1_5_completed\": true, \"b2_0_current_step\": 5149, \"b2_0_total_steps\": 6103, \"completed_b_values\": [0.5, 1, 1.5, 2, 3], \"current_b\": 5, \"total_steps\": 6103, \"current_step\": 3422, \"b5_0_progress_pct\": 56, \"eta_minutes\": 95, \"b2_0_completed\": true, \"b2_0_train_loss\": 10.621, \"b2_0_train_runtime_s\": 13034, \"b3_0_completed\": true, \"b3_0_train_loss\": 10.754, \"b3_0_train_runtime_s\": 13036, \"all_completed\": true, \"b1_0_train_loss\": 10.223, \"b1_5_train_loss\": 10.485, \"b5_0_train_loss\": 10.858, \"b0_5_runtime_s\": 13036, \"b1_0_runtime_s\": 12968, \"b1_5_runtime_s\": 14789, \"b2_0_runtime_s\": 13034, \"b3_0_runtime_s\": 13036, \"b5_0_runtime_s\": 13115, \"note\": \"eval_ppl missing - no --eval_data_path in batch script, post-hoc eval pending\", \"b0_5_eval_ppl\": 17.651, \"b1_0_eval_ppl\": 17.692, \"b1_5_eval_ppl\": 17.718, \"b2_0_eval_ppl\": 17.741, \"b3_0_eval_ppl\": 17.774, \"b5_0_eval_ppl\": 17.818, \"eval_holdout_tokens\": 4077068, \"best_b\": 0.5, \"best_eval_ppl\": 17.651}, \"conclusion\": \"success\"}, \"diagnostic_contamination100\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"detector_tfidf_lr\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"auc\": 0.939, \"accuracy\": 0.858, \"ece_raw\": 0.24, \"ece_calibrated\": 0.048, \"temperature_T\": 0.204, \"q_score_mean\": 0.6, \"q_score_std\": 0.374, \"q_score_median\": 0.707, \"mid_range_ratio\": 0.463}}}, \"count\": 88, \"total\": 88, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3636}}"
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
Key findings:

1. **rho02_adaptive_tau09_r2 crashed** - TypeError: `Trainer.__init__() got an unexpected keyword argument 'tokenizer'`. No training was completed. The registry already has it as `conclusion: "failed"`.

2. **rho02_uniform_seed42 exists** - PPL=17.336, which is the ρ=0.2 uniform baseline.

3. **rho02_adaptive_tau09_seed42 also exists** and also has `conclusion: "failed"` - likely the same bug.

So the experiment failed due to a code bug (transformers API change where `tokenizer` arg was renamed). No training metrics were produced.


Both attempts of the adaptive variant failed with the same issue. The fix would be switching from the deprecated `tokenizer` parameter to `processing_class` in the newer transformers API. Now I'll update the registry and write up the analysis report.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "ef32d5e6-58f8-4e9c-a0ae-6eff98fb1a80",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01K4BAdj4kdkj6wGJYbpD68A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11888,
      "cache_read_input_tokens": 28407,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11888
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

_source line 22_

实验 **rho02_adaptive_tau09_r2 崩溃了**，未完成任何训练。错误：`TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'`（transformers 库 API 变更，`tokenizer` 参数已重命名为 `processing_class`）。

Registry 已有数据：
- `rho02_uniform_seed42`: PPL=17.336（ρ=0.2 uniform baseline，已完成）
- `rho02_adaptive_tau09_seed42`: 同样 failed（相同 bug）

先读取现有 report.md，然后写入分析结果。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "5c92a3f5-741b-4a91-b64b-4e9443da4d00",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01K4BAdj4kdkj6wGJYbpD68A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11888,
      "cache_read_input_tokens": 28407,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11888
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

_source line 23_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01CxN8KDwof8V3sCRDpHdRKs`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "c5cbf197-0892-4b20-aed4-9967a9fa48cd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01K4BAdj4kdkj6wGJYbpD68A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11888,
      "cache_read_input_tokens": 28407,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11888
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

_source line 24 · 2026-05-17T11:19:12.947Z_

<details><summary>↩ Tool result · `toolu_01CxN8KDwof8V3sCRDpHdRKs`</summary>

````text
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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "354e29f6-7d0d-472e-8c03-f0a980663522",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 34
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01MBFrL7wYMkSS1wp4t4apAj`</summary>

```json
{
  "project": "provenance_weight_training",
  "file": "report.md",
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
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "603bd8f8-a069-4aca-af0d-fbce887ec705",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011L9CpFjTQ8R9UdHgrwQz8E",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1138,
      "cache_read_input_tokens": 40295,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1138
      },
      "output_tokens": 46,
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

_source line 26 · 2026-05-17T11:19:18.515Z_

<details><summary>↩ Tool result · `toolu_01MBFrL7wYMkSS1wp4t4apAj`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/report.md\", \"content\": \"# Handover — 2026-05-17\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| llama3b_uniform_seed42 | Uniform weighting baseline on Llama-3.2-3B establishes reference PPL for cross-model generalization experiment, enabling fair comparison with adaptive weighting on the same architecture and data. | — | — | — |\\n| llama3b_adaptive_seed42 | Adaptive b* generalizes across model architectures: Llama-3.2-3B with provenance-weighted training should show PPL improvement over uniform baseline proportional to Qwen3-0.6B results, confirming the method is not architecture-specific and dual-constraint b* transfers. | — | — | — |\\n| grid_b0_2_seed42 | Grid-b sweep b=0.2 on ρ=0.4 data, seed42. Interpolation between b=0.1 and b=0.3 to characterize PPL curve shape in low-b region. | — | — | — |\\n\\n## 待处理\\n- batchsize16_nmin8_r2（排队等待 GPU）\\n- grid_b0_3_seed456: b=0.3 is grid-optimal cross-seed (confirmed at seed42 PPL=17.640 < b=0.5 seed42 17.651). If seed456 also shows b=0.3 as best, confirms grid-best is not seed-specific and strengthens Claim 2 (adaptive ≈ grid-best).（已分配 westd-41312 GPU:cuda:1，等待提交）\\n\\n## 近期结论\\n- **rho02_adaptive_tau09_r2** (failed): —\\n- **random_reweight_seed123** (failed): —\\n- **batch_adaptive_tau_rho06_r2** (failed): —\\n\\n## 趋势\\n成功 49 / 负向 4 / 失败 17 / 共 83\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-30476: 无 GPU 信息\\nwestd-41312: 无 GPU 信息\\n\\n## 告警\\n- detector_modernbert: 已被终止 — unknown\\n- diagnostic_contamination100: 已被终止 — unknown\\n- adaptive_v2_seed42: 已被终止 — unknown\\n- adaptive_v2_seed123: 已被终止 — unknown\\n- adaptive_v2_seed456: 已被终止 — unknown\\n- grid_b_low_seed42: 训练失败 — unknown\\n- tau_0.6_seed42: 已被终止 — unknown\\n- bs8_seed42: 训练失败 — unknown\\n- bs8_nmin2_seed42: 训练失败 — unknown\\n- contamination_60_seed42: 训练失败 — unknown\\n- grid_b_low_seed42_r2: 训练失败 — unknown\\n- grid_b_low_seed42_r3: 训练失败 — unknown\\n- grid_b_low_serial_seed42: 已被终止 — unknown\\n- tau_05_nmin2_seed42: 已被终止 — unknown\\n- tau_06_nmin2_seed42: 已被终止 — unknown\\n- tau_07_nmin2_seed42: 已被终止 — unknown\\n- tau_09_nmin2_seed42: 已被终止 — unknown\\n- tau_095_nmin2_seed42: 已被终止 — unknown\\n- nmin5_seed42: 已被终止 — unknown\\n- batchsize16_nmin8_seed42: 训练失败 — unknown\\n- threshold_q07_seed42: 训练失败 — unknown\\n- random_reweight_seed42: 训练失败 — unknown\\n- rho02_adaptive_tau09_seed42: 训练失败 — unknown\\n- batch_adaptive_tau_rho06_seed42: 训练失败 — unknown\\n- bs8_auto_nmin_seed42: 训练失败 — unknown\\n- grid_b0_3_seed123: 训练失败 — unknown\\n- random_reweight_seed123: 训练失败 — unknown\\n- bs8_auto_nmin_r2: 训练失败 — unknown\\n- batch_adaptive_tau_rho06_r2: 训练失败 — unknown\\n- rho02_adaptive_tau09_r2: 训练失败 — unknown\\n\", \"total_chars\": 2608, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "837b0762-ee14-448d-bd2b-d0427ca84eb7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/report.md\\\", \\\"content\\\": \\\"# Handover — 2026-05-17\\\\n\\\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\\\n\\\\n## 运行中\\\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\\\n|--------|------|------|---------|-----|\\\\n| llama3b_uniform_seed42 | Uniform weighting baseline on Llama-3.2-3B establishes reference PPL for cross-model generalization experiment, enabling fair comparison with adaptive weighting on the same architecture and data. | — | — | — |\\\\n| llama3b_adaptive_seed42 | Adaptive b* generalizes across model architectures: Llama-3.2-3B with provenance-weighted training should show PPL improvement over uniform baseline proportional to Qwen3-0.6B results, confirming the method is not architecture-specific and dual-constraint b* transfers. | — | — | — |\\\\n| grid_b0_2_seed42 | Grid-b sweep b=0.2 on ρ=0.4 data, seed42. Interpolation between b=0.1 and b=0.3 to characterize PPL curve shape in low-b region. | — | — | — |\\\\n\\\\n## 待处理\\\\n- batchsize16_nmin8_r2（排队等待 GPU）\\\\n- grid_b0_3_seed456: b=0.3 is grid-optimal cross-seed (confirmed at seed42 PPL=17.640 < b=0.5 seed42 17.651). If seed456 also shows b=0.3 as best, confirms grid-best is not seed-specific and strengthens Claim 2 (adaptive ≈ grid-best).（已分配 westd-41312 GPU:cuda:1，等待提交）\\\\n\\\\n## 近期结论\\\\n- **rho02_adaptive_tau09_r2** (failed): —\\\\n- **random_reweight_seed123** (failed): —\\\\n- **batch_adaptive_tau_rho06_r2** (failed): —\\\\n\\\\n## 趋势\\\\n成功 49 / 负向 4 / 失败 17 / 共 83\\\\n\\\\n## 下一步\\\\n（无活跃 idea，请通过 ideas.md 添加）\\\\n\\\\n## 资源状态\\\\nwestd-30476: 无 GPU 信息\\\\nwestd-41312: 无 GPU 信息\\\\n\\\\n## 告警\\\\n- detector_modernbert: 已被终止 — unknown\\\\n- diagnostic_contamination100: 已被终止 — unknown\\\\n- adaptive_v2_seed42: 已被终止 — unknown\\\\n- adaptive_v2_seed123: 已被终止 — unknown\\\\n- adaptive_v2_seed456: 已被终止 — unknown\\\\n- grid_b_low_seed42: 训练失败 — unknown\\\\n- tau_0.6_seed42: 已被终止 — unknown\\\\n- bs8_seed42: 训练失败 — unknown\\\\n- bs8_nmin2_seed42: 训练失败 — unknown\\\\n- contamination_60_seed42: 训练失败 — unknown\\\\n- grid_b_low_seed42_r2: 训练失败 — unknown\\\\n- grid_b_low_seed42_r3: 训练失败 — unknown\\\\n- grid_b_low_serial_seed42: 已被终止 — unknown\\\\n- tau_05_nmin2_seed42: 已被终止 — unknown\\\\n- tau_06_nmin2_seed42: 已被终止 — unknown\\\\n- tau_07_nmin2_seed42: 已被终止 — unknown\\\\n- tau_09_nmin2_seed42: 已被终止 — unknown\\\\n- tau_095_nmin2_seed42: 已被终止 — unknown\\\\n- nmin5_seed42: 已被终止 — unknown\\\\n- batchsize16_nmin8_seed42: 训练失败 — unknown\\\\n- threshold_q07_seed42: 训练失败 — unknown\\\\n- random_reweight_seed42: 训练失败 — unknown\\\\n- rho02_adaptive_tau09_seed42: 训练失败 — unknown\\\\n- batch_adaptive_tau_rho06_seed42: 训练失败 — unknown\\\\n- bs8_auto_nmin_seed42: 训练失败 — unknown\\\\n- grid_b0_3_seed123: 训练失败 — unknown\\\\n- random_reweight_seed123: 训练失败 — unknown\\\\n- bs8_auto_nmin_r2: 训练失败 — unknown\\\\n- batch_adaptive_tau_rho06_r2: 训练失败 — unknown\\\\n- rho02_adaptive_tau09_r2: 训练失败 — unknown\\\\n\\\", \\\"total_chars\\\": 2608, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/report.md\", \"content\": \"# Handover — 2026-05-17\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| llama3b_uniform_seed42 | Uniform weighting baseline on Llama-3.2-3B establishes reference PPL for cross-model generalization experiment, enabling fair comparison with adaptive weighting on the same architecture and data. | — | — | — |\\n| llama3b_adaptive_seed42 | Adaptive b* generalizes across model architectures: Llama-3.2-3B with provenance-weighted training should show PPL improvement over uniform baseline proportional to Qwen3-0.6B results, confirming the method is not architecture-specific and dual-constraint b* transfers. | — | — | — |\\n| grid_b0_2_seed42 | Grid-b sweep b=0.2 on ρ=0.4 data, seed42. Interpolation between b=0.1 and b=0.3 to characterize PPL curve shape in low-b region. | — | — | — |\\n\\n## 待处理\\n- batchsize16_nmin8_r2（排队等待 GPU）\\n- grid_b0_3_seed456: b=0.3 is grid-optimal cross-seed (confirmed at seed42 PPL=17.640 < b=0.5 seed42 17.651). If seed456 also shows b=0.3 as best, confirms grid-best is not seed-specific and strengthens Claim 2 (adaptive ≈ grid-best).（已分配 westd-41312 GPU:cuda:1，等待提交）\\n\\n## 近期结论\\n- **rho02_adaptive_tau09_r2** (failed): —\\n- **random_reweight_seed123** (failed): —\\n- **batch_adaptive_tau_rho06_r2** (failed): —\\n\\n## 趋势\\n成功 49 / 负向 4 / 失败 17 / 共 83\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-30476: 无 GPU 信息\\nwestd-41312: 无 GPU 信息\\n\\n## 告警\\n- detector_modernbert: 已被终止 — unknown\\n- diagnostic_contamination100: 已被终止 — unknown\\n- adaptive_v2_seed42: 已被终止 — unknown\\n- adaptive_v2_seed123: 已被终止 — unknown\\n- adaptive_v2_seed456: 已被终止 — unknown\\n- grid_b_low_seed42: 训练失败 — unknown\\n- tau_0.6_seed42: 已被终止 — unknown\\n- bs8_seed42: 训练失败 — unknown\\n- bs8_nmin2_seed42: 训练失败 — unknown\\n- contamination_60_seed42: 训练失败 — unknown\\n- grid_b_low_seed42_r2: 训练失败 — unknown\\n- grid_b_low_seed42_r3: 训练失败 — unknown\\n- grid_b_low_serial_seed42: 已被终止 — unknown\\n- tau_05_nmin2_seed42: 已被终止 — unknown\\n- tau_06_nmin2_seed42: 已被终止 — unknown\\n- tau_07_nmin2_seed42: 已被终止 — unknown\\n- tau_09_nmin2_seed42: 已被终止 — unknown\\n- tau_095_nmin2_seed42: 已被终止 — unknown\\n- nmin5_seed42: 已被终止 — unknown\\n- batchsize16_nmin8_seed42: 训练失败 — unknown\\n- threshold_q07_seed42: 训练失败 — unknown\\n- random_reweight_seed42: 训练失败 — unknown\\n- rho02_adaptive_tau09_seed42: 训练失败 — unknown\\n- batch_adaptive_tau_rho06_seed42: 训练失败 — unknown\\n- bs8_auto_nmin_seed42: 训练失败 — unknown\\n- grid_b0_3_seed123: 训练失败 — unknown\\n- random_reweight_seed123: 训练失败 — unknown\\n- bs8_auto_nmin_r2: 训练失败 — unknown\\n- batch_adaptive_tau_rho06_r2: 训练失败 — unknown\\n- rho02_adaptive_tau09_r2: 训练失败 — unknown\\n\", \"total_chars\": 2608, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 27_

<details><summary>Logged reasoning block</summary>

```text
The report already shows rho02_adaptive_tau09_r2 as failed. The registry also already has it as `conclusion: "failed"`. 

The task asks me to:
1. Analyze the results - DONE: it crashed, no results
2. Update registry with metrics, conclusion, etc.
3. Write analysis to report

Since the experiment crashed during initialization (the `tokenizer` keyword arg bug in transformers), there are no metrics to report. The registry already has status=DONE and conclusion=failed.

Let me update the registry with the log_path and a note about the failure reason, then write a concise analysis section.


I need to fill in the remaining fields: log_path gets set to the crash log, and I'll document the error details in the metrics field so there's a record of what went wrong. Then I'll write up the analysis for the report.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "6d185e1c-5b9d-449f-80ba-dbfe981a6c67",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LdNH6ADa7x2dJME2PyyTBg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1485,
      "cache_read_input_tokens": 41433,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1485
      },
      "output_tokens": 9,
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

_source line 28_

Registry 已标记为 failed，report 也已列出。让我补充 log_path 和失败原因到 registry，并写入详细分析。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "ea1b2cfc-9a1d-4541-8127-3d2370cd038d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LdNH6ADa7x2dJME2PyyTBg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1485,
      "cache_read_input_tokens": 41433,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1485
      },
      "output_tokens": 9,
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

_source line 29_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01MZLmqH7CAyGoPytsNj6MK8`</summary>

```json
{
  "exp_id": "rho02_adaptive_tau09_r2",
  "field": "log_path",
  "value": "~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log",
  "project": "provenance_weight_training"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "af084696-730d-4a9e-8dce-18be3608d0da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LdNH6ADa7x2dJME2PyyTBg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1485,
      "cache_read_input_tokens": 41433,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1485
      },
      "output_tokens": 9,
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

_source line 30 · 2026-05-17T11:19:32.180Z_

<details><summary>↩ Tool result · `toolu_01MZLmqH7CAyGoPytsNj6MK8`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"rho02_adaptive_tau09_r2\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:34.927Z\", \"updated_at\": \"2026-05-17T11:19:31.742Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"submitted_at\": \"2026-05-17T11:15:37.586Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 142.8, \"gpu_hours\": 0.04}, \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:27.699Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:40.596896+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:18:00.344Z\", \"failure_reason\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9607}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "ddce6b7b-105f-4c1c-8471-f9dcf02ba082",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"rho02_adaptive_tau09_r2\\\", \\\"experiment\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-17T10:25:34.927Z\\\", \\\"updated_at\\\": \\\"2026-05-17T11:19:31.742Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\\\\\"\\\", \\\"server\\\": \\\"westd-30476\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"7951\\\", \\\"log_path\\\": \\\"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-17T11:15:37.586Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 142.8, \\\"gpu_hours\\\": 0.04}, \\\"server\\\": \\\"westd-30476\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"account\\\": \\\"root\\\", \\\"pid\\\": \\\"7951\\\", \\\"log_path\\\": \\\"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\\\", \\\"reproduce\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\\\\\"\\\", \\\"finished_at\\\": \\\"2026-05-17T11:16:27.699Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-17T11:16:40.596896+00:00\\\"}]}, \\\"conclusion\\\": \\\"failed\\\", \\\"completed_at\\\": \\\"2026-05-17T11:18:00.344Z\\\", \\\"failure_reason\\\": \\\"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\\\"}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9607}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"rho02_adaptive_tau09_r2\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:34.927Z\", \"updated_at\": \"2026-05-17T11:19:31.742Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"submitted_at\": \"2026-05-17T11:15:37.586Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 142.8, \"gpu_hours\": 0.04}, \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:27.699Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:40.596896+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:18:00.344Z\", \"failure_reason\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\"}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9607}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01NMDtFSmEaGXJm33oHYNw22`</summary>

```json
{
  "exp_id": "rho02_adaptive_tau09_r2",
  "field": "metrics",
  "value": {
    "error": "TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'",
    "error_stage": "initialization",
    "training_completed": false,
    "note": "Crashed before any training. Same bug as rho02_adaptive_tau09_seed42. Fix: replace tokenizer= with processing_class= in pretrain_weighted.py line ~101."
  },
  "project": "provenance_weight_training"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "b813b1b3-292f-44dd-a782-afd8d0fdd6ad",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LdNH6ADa7x2dJME2PyyTBg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1485,
      "cache_read_input_tokens": 41433,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1485
      },
      "output_tokens": 9,
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

_source line 32 · 2026-05-17T11:19:34.667Z_

<details><summary>↩ Tool result · `toolu_01NMDtFSmEaGXJm33oHYNw22`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"exp_id\": \"rho02_adaptive_tau09_r2\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:34.927Z\", \"updated_at\": \"2026-05-17T11:19:34.469Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"submitted_at\": \"2026-05-17T11:15:37.586Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 142.8, \"gpu_hours\": 0.04}, \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:27.699Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:40.596896+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:18:00.344Z\", \"failure_reason\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\", \"metrics\": {\"error\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\", \"error_stage\": \"initialization\", \"training_completed\": false, \"note\": \"Crashed before any training. Same bug as rho02_adaptive_tau09_seed42. Fix: replace tokenizer= with processing_class= in pretrain_weighted.py line ~101.\"}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5172}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "697749d5-0c2a-4802-8637-552817e24e7a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"exp_id\\\": \\\"rho02_adaptive_tau09_r2\\\", \\\"experiment\\\": {\\\"status\\\": \\\"DONE\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-17T10:25:34.927Z\\\", \\\"updated_at\\\": \\\"2026-05-17T11:19:34.469Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\\\\\"\\\", \\\"server\\\": \\\"westd-30476\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"7951\\\", \\\"log_path\\\": \\\"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\\\", \\\"submitted_at\\\": \\\"2026-05-17T11:15:37.586Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 142.8, \\\"gpu_hours\\\": 0.04}, \\\"server\\\": \\\"westd-30476\\\", \\\"gpu\\\": \\\"cuda:3\\\", \\\"account\\\": \\\"root\\\", \\\"pid\\\": \\\"7951\\\", \\\"log_path\\\": \\\"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\\\", \\\"reproduce\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\\\\\"\\\", \\\"finished_at\\\": \\\"2026-05-17T11:16:27.699Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-17T11:16:40.596896+00:00\\\"}]}, \\\"conclusion\\\": \\\"failed\\\", \\\"completed_at\\\": \\\"2026-05-17T11:18:00.344Z\\\", \\\"failure_reason\\\": \\\"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\\\", \\\"metrics\\\": {\\\"error\\\": \\\"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\\\", \\\"error_stage\\\": \\\"initialization\\\", \\\"training_completed\\\": false, \\\"note\\\": \\\"Crashed before any training. Same bug as rho02_adaptive_tau09_seed42. Fix: replace tokenizer= with processing_class= in pretrain_weighted.py line ~101.\\\"}}}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.5172}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"exp_id\": \"rho02_adaptive_tau09_r2\", \"experiment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:34.927Z\", \"updated_at\": \"2026-05-17T11:19:34.469Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"submitted_at\": \"2026-05-17T11:15:37.586Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 142.8, \"gpu_hours\": 0.04}, \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:27.699Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:40.596896+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:18:00.344Z\", \"failure_reason\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\", \"metrics\": {\"error\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\", \"error_stage\": \"initialization\", \"training_completed\": false, \"note\": \"Crashed before any training. Same bug as rho02_adaptive_tau09_seed42. Fix: replace tokenizer= with processing_class= in pretrain_weighted.py line ~101.\"}}}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5172}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 33_

现在写入分析报告。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "842903b3-1823-4c0b-b325-00f2b474a468",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MJDmSnCxsrHUmZWR1P6DQL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2170,
      "cache_read_input_tokens": 42918,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2170
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

### Tool call

_source line 34_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__save_project_file · `toolu_01CPQcQ8WPmi8bWhdDHwvicC`</summary>

````json
{
  "project": "provenance_weight_training",
  "file": "memory.md",
  "content": "# Memory\n\n## rho02_adaptive_tau09_r2 分析 (2026-05-17)\n\n### 结果\n- **Status**: FAILED — 初始化阶段崩溃，无训练数据产出\n- **错误**: `TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'`\n- **原因**: westd-30476 上的 transformers 版本已弃用 `tokenizer` 参数，需改用 `processing_class`\n- **影响范围**: 同一 bug 影响了 rho02_adaptive_tau09_seed42、bs8_auto_nmin_r2、batch_adaptive_tau_rho06_r2 等多个实验\n\n### 对 Claim 3 的影响\n- **Claim 3 (proportion-robustness) 无法验证** — 缺少 ρ=0.2 adaptive 的 PPL 数据\n- 已有 baseline: rho02_uniform_seed42 PPL=17.336（ρ=0.2 uniform）\n- 对比参考: ρ=0.4 adaptive PPL=17.644, ρ=0.4 uniform PPL≈17.69\n- 需要修复 `pretrain_weighted.py` 第~101行的 `tokenizer=` → `processing_class=` 后重跑\n\n### 修复建议\n在 `/root/provenance_weight_training/training/pretrain_weighted.py` 第101行附近：\n```python\n# 旧代码\nsuper().__init__(**kwargs)  # kwargs 中含 tokenizer=...\n# 修复：将传入的 tokenizer 关键字替换为 processing_class\n```\n\n### 相关实验对比表（ρ=0.2 数据集）\n| 实验 | 方法 | PPL | 状态 |\n|------|------|-----|------|\n| rho02_uniform_seed42 | uniform | 17.336 | success |\n| rho02_adaptive_tau09_seed42 | adaptive τ=0.9 | — | failed (同一 bug) |\n| rho02_adaptive_tau09_r2 | adaptive τ=0.9 (retry) | — | failed (同一 bug) |\n"
}
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "86a814b7-54e5-4644-9e52-fe5557d47161",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MJDmSnCxsrHUmZWR1P6DQL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2170,
      "cache_read_input_tokens": 42918,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2170
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

### Tool result

_source line 35 · 2026-05-17T11:19:53.155Z_

<details><summary>↩ Tool result · `toolu_01CPQcQ8WPmi8bWhdDHwvicC`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/memory.md\", \"saved\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "17331b59-0f30-4348-b621-296141e63428",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/memory.md\\\", \\\"saved\\\": true}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/memory.md\", \"saved\": true}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 36_

## rho02_adaptive_tau09_r2 分析

**Status**: FAILED — 初始化阶段崩溃，零训练产出。

**错误**: `TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'`
- `pretrain_weighted.py:101` 中 `WeightedTrainer.__init__` 传入了 `tokenizer=` 关键字
- westd-30476 上的 transformers 版本已将该参数重命名为 `processing_class`
- 同一 bug 导致 `rho02_adaptive_tau09_seed42`、`bs8_auto_nmin_r2`、`batch_adaptive_tau_rho06_r2` 等多个实验全部失败

**对 Claim 3 的影响**:
- ρ=0.2 adaptive 无数据，Claim 3 (proportion-robustness) **无法验证**
- 已有 baseline: `rho02_uniform_seed42` PPL=**17.336**
- 对比参考: ρ=0.4 adaptive PPL=17.644 vs ρ=0.4 uniform PPL≈17.69

**Registry 已更新**: log_path、metrics（含错误信息）、conclusion=failed。

**修复方案**: `pretrain_weighted.py` 第~101行将 `tokenizer=` 替换为 `processing_class=`，然后重提交实验。这个 fix 同时会解决其他因相同 bug 失败的实验。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "uuid": "af030ef4-92d8-4cce-8f79-577895079efe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01N6fENbUpgv2iSLTCbL2PaC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 794,
      "cache_read_input_tokens": 45088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 794
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

_source line 37_

## rho02_adaptive_tau09_r2 分析

**Status**: FAILED — 初始化阶段崩溃，零训练产出。

**错误**: `TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'`
- `pretrain_weighted.py:101` 中 `WeightedTrainer.__init__` 传入了 `tokenizer=` 关键字
- westd-30476 上的 transformers 版本已将该参数重命名为 `processing_class`
- 同一 bug 导致 `rho02_adaptive_tau09_seed42`、`bs8_auto_nmin_r2`、`batch_adaptive_tau_rho06_r2` 等多个实验全部失败

**对 Claim 3 的影响**:
- ρ=0.2 adaptive 无数据，Claim 3 (proportion-robustness) **无法验证**
- 已有 baseline: `rho02_uniform_seed42` PPL=**17.336**
- 对比参考: ρ=0.4 adaptive PPL=17.644 vs ρ=0.4 uniform PPL≈17.69

**Registry 已更新**: log_path、metrics（含错误信息）、conclusion=failed。

**修复方案**: `pretrain_weighted.py` 第~101行将 `tokenizer=` 替换为 `processing_class=`，然后重提交实验。这个 fix 同时会解决其他因相同 bug 失败的实验。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 97594,
  "duration_api_ms": 92816,
  "num_turns": 12,
  "stop_reason": "end_turn",
  "session_id": "13085807-3333-4f5b-9aea-8323a8e4634b",
  "total_cost_usd": 0.43898374999999995,
  "usage": {
    "input_tokens": 14,
    "cache_creation_input_tokens": 34041,
    "cache_read_input_tokens": 262419,
    "output_tokens": 3726,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 34041,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 411,
        "cache_read_input_tokens": 45088,
        "cache_creation_input_tokens": 794,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 794
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1678,
      "outputTokens": 24,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0017980000000000001,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 14,
      "outputTokens": 3726,
      "cacheReadInputTokens": 262419,
      "cacheCreationInputTokens": 34041,
      "webSearchRequests": 0,
      "costUSD": 0.43718575,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "c62595da-ec71-4e4d-926e-2a5668dbca77"
}
```

</details>

---

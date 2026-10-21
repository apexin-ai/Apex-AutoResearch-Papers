# research paper results prep

**Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 24
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/workers/worker_research_paper-results-prep_20260514T083314.log`
- **Structured JSON:** [`f8e8acd6fa5535bb696e.json`](../../sessions/f8/f8e8acd6fa5535bb696e.json)

## Before a recorded user message

24 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### Runtime record

_source line 2_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1778761800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "5fdce6ec-f8dd-479c-9942-dbbd90706ced",
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba"
}
```

---

### System

_source line 3_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration",
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
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
  "uuid": "35206586-63ff-493f-9368-ae1b162a76a7",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-13-projects-contamcal-irt-calibration/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Assistant

_source line 4_

I'll start by reading the registry and the exp004 analysis file in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "a883fc8a-002b-4af4-bd8c-77ba43259844",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MGRCxYjokqptr2KPzCKKYG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11562,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11562
      },
      "output_tokens": 2,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01SNYf8Aq9a3E7tNumKG6RqV`</summary>

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
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "f94eb8e3-1104-433f-b83b-d4c8d4f936b6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MGRCxYjokqptr2KPzCKKYG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11562,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11562
      },
      "output_tokens": 2,
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

_source line 6 · 2026-05-14T08:33:46.851Z_

<details><summary>↩ Tool result · `toolu_01SNYf8Aq9a3E7tNumKG6RqV`</summary>

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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "04f53f6c-306a-4134-929d-b16c8bb8b4ab",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
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
Now let me read the registry and the exp004 analysis file in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "fab2f431-748b-4636-9eff-a63c4e0a8f09",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0183TSTvTrsC384WGzTQAyZr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23403,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 48,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01NZoP3EZvJ855x2HuTyyFDW`</summary>

```json
{
  "filters": {
    "status": "DONE",
    "conclusion": "success"
  },
  "project": "contamcal-irt-calibration",
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
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "03ff3fbd-eb1a-4f28-9f82-d69c5ef9c099",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0183TSTvTrsC384WGzTQAyZr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23403,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 48,
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

<details open><summary>🔧 Tool call — Read · `toolu_01She69xmaa5y5FPYVvrfGGU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/exp004_incremental_analysis.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "ed5991a8-61f8-48ce-aea8-00a6e8395458",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0183TSTvTrsC384WGzTQAyZr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23403,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 48,
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

_source line 10 · 2026-05-14T08:33:51.415Z_

<details><summary>↩ Tool result · `toolu_01NZoP3EZvJ855x2HuTyyFDW`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"exp_001_eval_05B_d005\": {\"created_at\": \"2026-05-14T01:17:07.820Z\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d005_s42\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42/lora_adapter\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python /root/contamcal-irt-calibration/exp001/evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d005_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\", \"data_count\": 0, \"data_path\": \"d005 contaminated checkpoint\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": \"cuda:1\", \"hypothesis\": \"0.5B 5% dosage contaminated model eval on 4 benchmarks — low-dosage contamination detection sensitivity test\", \"log_path\": \"/root/runs/contamcal-irt-calibration/exp_001_eval_05B_d005.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_sft_d005_05B\", \"pid\": \"255322\", \"seed\": 42, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T08:01:35.087Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T06:44:49.861Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:44:50.409Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T06:44:51.900757+00:00\"}]}, \"notes\": \"⚠️ legacy mc_format — 仅供诊断参考，正式分析需用 aligned 格式重跑 (D017 延伸决策)。\"}, \"exp_001_eval_05B_d100_v5\": {\"created_at\": \"2026-05-14T02:39:57.338Z\", \"hypothesis\": \"100% dosage 0.5B s42 contaminated eval (v5, 最终干净提交)\", \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d100_s42\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python evaluate.py ...\\\"\", \"data_count\": 4, \"data_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42/lora_adapter\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d100_v5.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_sft_d100_05B\", \"pid\": \"266780\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T02:39:57.046Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 17504.7, \"gpu_hours\": 4.86}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T08:01:34.216Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T07:30:37.450Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T07:30:41.628489+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.2322, \"gsm8k\": 0.3571, \"arc_challenge\": 0.227, \"humaneval_pass1\": 0.0854}, \"completed_at\": \"2026-05-14T07:31:41.784Z\", \"notes\": \"结果文件: /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d100_s42/。⚠️ legacy mc_format — 仅供诊断参考，正式分析需用 aligned 格式重跑 (D017 延伸决策)。d100 MC 分数低于 d000 baseline (MMLU -17.3pp, ARC -15.1pp) 系格式不匹配所致。\"}, \"exp_001_eval_05B_d000_s42_v5\": {\"created_at\": \"2026-05-14T02:39:41.292Z\", \"hypothesis\": \"0% dosage 0.5B s42 baseline eval (v5, 最终干净提交)\", \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s42\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python evaluate.py ...\\\"\", \"data_count\": 4, \"data_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42/lora_adapter\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s42_v5.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_sft_0pct_05B\", \"pid\": \"266511\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T02:39:41.108Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 17519.2, \"gpu_hours\": 4.87}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T08:01:31.086Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T07:30:31.429Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T07:30:35.061894+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.4049, \"gsm8k\": 0.3647, \"arc_challenge\": 0.378, \"humaneval\": 0.1098}, \"completed_at\": \"2026-05-14T07:31:40.285Z\", \"notes\": \"结果文件: /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s42/。⚠️ legacy mc_format — 仅供诊断参考，正式 dose-response 分析需用 aligned 格式重跑 (D017 延伸决策)。\"}, \"exp_001_sft_d100_15B_v2\": {\"created_at\": \"2026-05-14T01:17:47.114Z\", \"parent\": \"exp_001_sft_d100_15B\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d100_s42\", \"command\": \"python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d100_s42 --seed 42 --gpu 0 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\", \"data_count\": 66533, \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl\", \"gpu\": [\"cuda:0\"], \"hypothesis\": \"100% dosage contaminated SFT on Qwen2.5-1.5B (seed=42): v2 retry with batch_size=1 to fix OOM. Maximum contamination for 1.5B scale.\", \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_d100_15B_v2.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"251924\", \"seed\": 42, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T07:39:22.684Z\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T07:39:22.684Z\"}, \"exp_001_eval_3B_d000_s42\": {\"completed_at\": \"2026-05-13T23:43:16.876Z\", \"created_at\": \"2026-05-13T23:36:54.086Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"v1 --gpu param caused evaluate.py crash. Resubmitted without --gpu.\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T06:47:56.373112+00:00\"}]}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"hypothesis\": \"0% dosage 3B s42 baseline evaluation on 4 benchmarks (mmlu, gsm8k, arc_challenge, humaneval) to establish ground-truth scores for calibration error computation\", \"notes\": \"v1 failed (--gpu bug), v2 resubmitted with CUDA_VISIBLE_DEVICES. PID 249294 confirmed running on GPU 1 (cron monitored).\", \"parent\": \"exp_001_sft_0pct_3B\", \"retry_count\": 1, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": 26000, \"data_path\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:1\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_3B_d000_s42.log\", \"model_name\": \"Qwen2.5-3B\", \"pid\": \"249294\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T08:54:00Z\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T07:03:36.187Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T06:47:54.565Z\"}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.634, \"gsm8k\": 0.117, \"arc\": 0.822, \"humaneval\": 0.116}}, \"exp_001_eval_3B_d000_s123\": {\"created_at\": \"2026-05-14T00:18:07.960Z\", \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": 26000, \"data_path\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_3B_d000_s123.log\", \"model_name\": \"Qwen2.5-3B\", \"pid\": \"242581\", \"seed\": 123, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T00:18:36.008Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 15706.2, \"gpu_hours\": 4.36, \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T04:44:59.509Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T04:39:50.139Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:39:53.713806+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"mmlu_accuracy\": 0.6362, \"gsm8k_exact_match\": 0.1759, \"arc_challenge_accuracy\": 0.8294, \"humaneval_pass_at_1\": 0.0854}, \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123\", \"completed_at\": \"2026-05-14T04:40:22.199Z\"}, \"exp_001_eval_15B_d000_s123\": {\"completed_at\": \"2026-05-13T23:39:26.418Z\", \"created_at\": \"2026-05-13T22:30:41.501Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:42:53.247372+00:00\"}]}, \"failure_reason\": \"EXIT_CODE=2: --gpu 0 参数导致 evaluate.py 崩溃。重跑时需去掉 --gpu 参数。\", \"retry_count\": 1, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123\", \"checkpoint_source\": \"exp_001_sft_0pct_15B_s123\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": \"4 benchmarks\", \"data_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123/\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:5\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s123.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"250600\", \"seed\": 123, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T00:59:22.874Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 13475.7, \"gpu_hours\": 3.74}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T04:43:58.619Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T04:42:48.051Z\"}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.5762, \"gsm8k\": 0.6331, \"arc_challenge\": 0.7662, \"humaneval_pass@1\": 0.1707}}, \"exp_001_eval_15B_d000_s42_v2\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter\", \"completed_at\": \"2026-05-14T03:12:11.373Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-14T00:23:20.112Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T03:09:29.636850+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s42_v2.log\", \"metrics\": {\"arc_challenge_accuracy\": 0.7756, \"arc_challenge_correct\": 909, \"arc_challenge_total\": 1172, \"gsm8k_correct\": 840, \"gsm8k_exact_match\": 0.6368, \"gsm8k_total\": 1319, \"humaneval_correct\": 21, \"humaneval_pass_at_1\": 0.128, \"humaneval_total\": 164, \"mmlu_accuracy\": 0.5753, \"mmlu_correct\": 8079, \"mmlu_total\": 14042}, \"reproduce\": {\"finished_at\": \"2026-05-14T03:09:26.521Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": 26000, \"data_path\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:4\"], \"gpu_hours\": 2.81, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s42_v2.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"243290\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T00:23:34.122Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 10117.3}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T03:12:11.373Z\"}, \"exp_001_eval_05B_d000_s123\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter\", \"completed_at\": \"2026-05-14T01:29:09.875Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T22:30:40.455Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T01:26:32.038369+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s123.log\", \"metrics\": {\"arc_challenge_accuracy\": 0.3976, \"gsm8k_exact_match\": 0.3404, \"humaneval_pass_at_1\": 0.1037, \"mmlu_accuracy\": 0.4182}, \"reproduce\": {\"finished_at\": \"2026-05-14T01:26:29.607Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter\", \"command\": \"python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\", \"data_count\": null, \"data_path\": \"d000 (baseline, no contamination)\", \"eval_data\": \"mmlu gsm8k arc_challenge humaneval\", \"gpu\": [\"cuda:2\"], \"gpu_hours\": 2.72, \"gpu_ids\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s123.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_train_05B_d000_s123\", \"pid\": \"229516\", \"seed\": 123, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T22:45:48.124Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 9801.8}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T01:29:09.875Z\"}, \"exp_001_sft_d005_05B_v3\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42\", \"completed_at\": \"2026-05-14T00:58:15.977Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T23:52:39.321Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T00:55:43.945907+00:00\"}]}, \"hypothesis\": \"5% dosage contaminated SFT on Qwen2.5-0.5B (seed=42): v3 retry with correct --gpu 5 (v1/v2 OOM due to --gpu 0 conflicting with d100 on GPU 0). Minimum contamination level for dose-response threshold.\", \"metrics\": {\"checkpoint_size_mb\": 166, \"entropy\": 1.5874, \"epoch\": 1, \"exit_code\": 0, \"final_loss\": 1.478, \"lora_adapter_size_mb\": 33.6, \"mean_train_loss\": 1.5424, \"num_tokens\": 19657865, \"token_accuracy\": 0.667, \"total_steps\": 3177, \"train_samples_per_second\": 15.09, \"train_steps_per_second\": 0.943, \"training_time_min\": 56.14, \"vs_baseline_0pct\": {\"baseline_final_loss\": 1.4894, \"baseline_mean_train_loss\": 1.5388, \"baseline_token_accuracy\": 0.682, \"baseline_training_time_min\": 52.9, \"delta_final_loss\": -0.0114, \"delta_mean_train_loss\": 0.0036, \"delta_token_accuracy\": -0.015, \"delta_training_time_min\": 3.24}}, \"notes\": \"dosage 数据已完整（含 MMLU+ARC+GSM8K，May 14 07:16 重新生成）。v3 已修复 --gpu 5（v1/v2 均为 --gpu 0 错误）。此 run 使用 ALL paraphrases（含 QC fail），属于 \\\"noisy contamination\\\" condition。\", \"parent\": \"exp_001_sft_d005_05B\", \"reproduce\": {\"finished_at\": \"2026-05-14T00:55:38.416Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"N/A (SFT retry, not eval)\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_005.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42 --seed 42 --gpu 5 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": 50826, \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_005.jsonl\", \"eval_data\": \"N/A (SFT retry, not eval)\", \"gpu\": [\"cuda:5\"], \"gpu_hours\": 1.0, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_d005_05B_v3.log\", \"model_name\": \"Qwen2.5-0.5B\", \"pid\": \"239729\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T23:58:01.548Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 3614.4}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:58:15.977Z\"}, \"exp_001_sft_d100_05B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42\", \"completed_at\": \"2026-05-14T00:53:49.656Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T23:36:13.403Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T00:50:19.949448+00:00\"}]}, \"gpu\": \"cuda:0\", \"hypothesis\": \"100% dosage contaminated SFT on Qwen2.5-0.5B (seed=42): maximum contamination level to establish upper bound of calibration error; paired with d005 for min-max comparison\", \"log_path\": \"/root/runs/contamcal-irt-calibration/exp_001_sft_d100_05B.log\", \"metrics\": {\"exit_code\": 0, \"final_loss\": 1.5943, \"mean_train_loss\": 1.5662, \"num_tokens\": 21575068, \"token_accuracy\": 0.666, \"total_steps\": 4160, \"train_samples_per_second\": 16.09, \"train_steps_per_second\": 1.006, \"training_time_min\": 68.9, \"vs_baseline_0pct\": {\"accuracy_delta\": \"-0.016 (-2.3%)\", \"loss_delta\": \"+0.0274 (+1.8%)\", \"time_delta\": \"+16min (+30%)\"}}, \"notes\": \"dosage 数据已完整（含 MMLU+ARC+GSM8K，May 14 07:16 重新生成）。data_meta: arc=1172, gsm8k=1319, mmlu=14042, total_contam=16533。此 run 使用 ALL paraphrases（含 QC fail），属于 \\\"noisy contamination\\\" condition。\", \"pid\": \"235243\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42 --seed 42 --gpu 0 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"finished_at\": \"2026-05-14T00:50:16.569Z\", \"gpu\": \"cuda:0\", \"server\": \"cqa1-21977\", \"started_at\": \"2026-05-13T23:38:41.749Z\", \"training_hours\": 1.19}, \"retry_count\": 0, \"server\": \"cqa1-21977\", \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42 --seed 42 --gpu 0 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:0\"], \"gpu_hours\": 1.23, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_d100_05B.log\", \"pid\": \"235243\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T23:39:51.510Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 4438.1}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:55:14.218Z\"}, \"exp_001_sft_0pct\": {\"checkpoint_path\": \"N/A (parent entry)\", \"completed_at\": \"2026-05-14T00:36:52.832Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:26:42.106Z\", \"hypothesis\": \"0% dosage (clean) SFT baselines on Qwen2.5-0.5B/1.5B/3B establish ground-truth benchmark scores for calibration error computation; LoRA r=16 alpha=32 1-epoch training on pure instruction data should preserve base model capability\", \"log_path\": \"N/A (parent entry)\", \"notes\": \"Parent entry for 3 sub-experiments (05B/15B/3B). All confirmed running.\", \"retry_count\": 0, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:36:52.832Z\"}, \"exp_001_sft_0pct_3B_s123\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123\", \"completed_at\": \"2026-05-14T00:23:18.290Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T20:39:01.606Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T00:16:17.727184+00:00\"}]}, \"hypothesis\": \"0% dosage clean baseline Qwen2.5-3B seed=123 (second seed for variance estimation)\", \"metrics\": {\"adapter_model_mb\": 114, \"adapter_size_mb\": 488, \"checkpoint_size_mb\": 488, \"epochs\": 1, \"final_loss\": 1.114, \"mean_token_accuracy\": 0.7505, \"mean_train_loss\": 1.1309, \"steps_completed\": 3125, \"total_steps\": 3125, \"total_tokens\": 19555717, \"train_samples_per_second\": 3.91, \"training_time_min\": 213.1}, \"notes\": \"OOM 修复后重提交 --gpu 3 (物理 GPU 3)。Worker 确认 PID 216249 训练中，ETA ~3.4h\", \"reproduce\": {\"finished_at\": \"2026-05-14T00:16:04.357Z\"}, \"retry_count\": 0, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123 --seed 123 --gpu 3 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": \"50000\", \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B_s123.log\", \"model_name\": \"Qwen2.5-3B\", \"pid\": \"216935\", \"seed\": 123, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:23:18.290Z\"}, \"exp_001_sft_0pct_3B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42\", \"completed_at\": \"2026-05-13T23:25:49.016Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:44:40.471Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-13T23:23:43.393661+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B.log\", \"metrics\": {\"adapter_size_mb\": 115, \"checkpoint_size_mb\": 488, \"exit_code\": 0, \"final_loss\": 1.0736, \"mean_train_loss\": 1.1306, \"steps\": \"3125/3125\", \"token_accuracy\": 0.734, \"training_time_min\": 214.7}, \"reproduce\": {\"finished_at\": \"2026-05-13T23:23:41.844Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42 --seed 42 --gpu 5 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:5\"], \"gpu_hours\": 3.69, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B.log\", \"pid\": \"210666\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T19:44:40.431Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 13268.6}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T23:25:49.016Z\"}, \"exp_001_sft_injection\": {\"completed_at\": \"2026-05-13T23:14:30.258Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T17:28:01.546Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_failed\", \"ts\": \"2026-05-13T19:18:08.635006+00:00\"}, {\"action\": \"manual_fix\", \"event\": \"status_rollback\", \"reason\": \"Cron misidentified old PID as dead → auto-failed. 3 paraphrase processes (GPU 0-2) still running. Rolled back DONE/failed → RUNNING per Director instruction.\", \"ts\": \"2026-05-13T19:32:00.000Z\"}, {\"action\": \"agent\", \"event\": \"on_failed\", \"ts\": \"2026-05-13T23:14:43.962197+00:00\"}]}, \"failure_reason\": \"\", \"hypothesis\": \"Controlled SFT contamination injection produces dose-dependent score inflation on contaminated benchmarks; 4PL+γ IRT can recover true (uncontaminated) performance from calibrated scores with proper uncertainty bounds\", \"metrics\": {\"arc_qc_pass\": 697, \"arc_qc_rate\": 0.595, \"arc_total\": 1172, \"gsm8k_qc_pass\": 228, \"gsm8k_qc_rate\": 0.173, \"gsm8k_total\": 1319, \"humaneval_total\": 164, \"mmlu_qc_pass\": 6596, \"mmlu_qc_rate\": 0.47, \"mmlu_total\": 14042}, \"notes\": \"MMLU paraphrase 3-attempt QC 重试流程: Attempt 1 ✅ (878 batches, 4112/14042 QC pass 29.3%, ~90min). Attempt 2 进行中 (v2重启, 439 batches total, 进度~22%). Attempt 3 待定. 输出在全部 attempt 结束后一次性写出 mmlu_paraphrases.json. GSM8K ✅ 1319条(QC 17.3%), ARC ✅ 1172条(QC 59.5%).\", \"reproduce\": {\"finished_at\": \"2026-05-13T23:14:29.355Z\"}, \"retry_count\": 0, \"spec\": {\"command\": \"Phase 1 paraphrase: GPU 0 MMLU (PID 204467 v3, vLLM bs=16). GSM8K + ARC completed.\", \"data_count\": \"45 SFT runs + 90 eval runs (original+paraphrased)\", \"data_path\": \"MMLU+GSM8K+ARC-Challenge+HumanEval paraphrases → SFT data mixing\", \"gpu\": \"cuda:0 (MMLU vLLM, still running). cuda:1/2 freed (GSM8K+ARC done).\", \"model_name\": \"Qwen2.5-0.5B/1.5B/3B (LoRA SFT), Qwen2.5-7B-Instruct (paraphrase)\", \"note\": \"GSM8K: 1319 paraphrases (228 QC pass, 17.3%). ARC: 1172 paraphrases (697 QC pass, 59.5%). MMLU: Attempt 1 done (878 batches, 29.3% QC), Attempt 2 in progress (439 batches total, ~22%), Attempt 3 pending. HumanEval: done (appendix per D009).\", \"pid\": \"204467\", \"seed\": \"42,123,456\", \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T23:21:54.827Z\"}, \"exp_001_sft_0pct_15B_s123\": {\"completed_at\": \"2026-05-13T22:30:26.882Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T20:35:07.346Z\", \"hypothesis\": \"0% dosage clean baseline Qwen2.5-1.5B seed=123 (second seed for variance estimation)\", \"metrics\": {\"token_acc\": 0.731, \"train_loss\": 1.2602, \"train_time_min\": 101.5}, \"notes\": \"OOM 修复后重提交 --gpu 2 (物理 GPU 2)。Worker 确认 PID 216106 训练中 (1/3125 steps, ~2.58s/it)\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123 --seed 123 --gpu 2 --batch-size 2 --grad-accum 8 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": \"50000\", \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\", \"gpu\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B_s123.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"216111\", \"seed\": 123, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T22:30:26.882Z\"}, \"exp_001_sft_0pct_05B_s123\": {\"completed_at\": \"2026-05-13T22:30:25.819Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T20:35:04.879Z\", \"hypothesis\": \"0% dosage clean baseline Qwen2.5-0.5B seed=123 (second seed for variance estimation)\", \"metrics\": {\"token_acc\": 0.676, \"train_loss\": 1.5393, \"train_time_min\": 54.5}, \"notes\": \"OOM 修复后重提交 --gpu 1 (物理 GPU 1)。Worker 确认 PID 216028 训练中 (2/3125 steps, ~1.87s/it)\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123 --seed 123 --gpu 1 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": \"50000\", \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\", \"gpu\": [\"cuda:1\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B_s123.log\", \"model_name\": \"Qwen2.5-0.5B\", \"pid\": \"216033\", \"seed\": 123, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T22:30:25.819Z\"}, \"exp_001_sft_0pct_15B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42\", \"completed_at\": \"2026-05-13T21:27:59.348Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:39:48.369Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-13T21:25:42.551081+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B.log\", \"metrics\": {\"adapter_size_mb\": 71, \"checkpoint_size_mb\": 313, \"exit_code\": 0, \"final_loss\": 1.2039, \"mean_train_loss\": 1.2599, \"steps\": \"3125/3125\", \"token_accuracy\": 0.711, \"training_time_min\": 101.5}, \"reproduce\": {\"finished_at\": \"2026-05-13T21:25:40.979Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42 --seed 42 --gpu 4 --batch-size 2 --grad-accum 8 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:4\"], \"gpu_hours\": 1.78, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B.log\", \"pid\": \"210116\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T19:41:11.760Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 6407.6}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T21:27:59.348Z\"}, \"exp_001_sft_0pct_05B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42\", \"completed_at\": \"2026-05-13T20:36:06.744Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:35:01.170Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-13T20:33:54.496690+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B.log\", \"metrics\": {\"adapter_size_mb\": 34, \"checkpoint_size_mb\": 166, \"exit_code\": 0, \"final_loss\": 1.4894, \"mean_train_loss\": 1.5388, \"steps\": \"3125/3125\", \"token_accuracy\": 0.682, \"training_time_min\": 52.9}, \"reproduce\": {\"finished_at\": \"2026-05-13T20:33:53.420Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42 --seed 42 --gpu 3 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:3\"], \"gpu_hours\": 0.98, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B.log\", \"pid\": \"208933\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T19:37:23.024Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 3523.7}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T20:37:01.562Z\"}, \"mvp_sim_confounding\": {\"completed_at\": \"2026-05-13T16:28:42.378Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T04:39:19.345Z\", \"hypothesis\": \"4PL+γ IRT model can still separate γ from θ when exposure is confounded with ability (corr≈0.4); if not, need model-level random effect for exposure\", \"metrics\": {\"actual_confound_corr\": 0.3814, \"divergent_pct\": 0, \"fit_time_sec\": 832, \"gamma_ci_covers_true\": true, \"gamma_ci_excludes_zero\": true, \"gamma_mean\": 0.5386, \"gamma_rel_bias\": 0.0771, \"max_rhat\": 1.007, \"min_ess\": 1371.9, \"overall\": \"PASS\", \"theta_corr\": 0.9733, \"theta_residual_exp_corr\": 0.0582, \"theta_rmse\": 0.2407}, \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"artifacts/mvp_simulation/p2_confounding_results.json\", \"command\": \"python run_p2_confounding.py\", \"data_count\": \"50 models x 300 items = 15000 responses\", \"data_path\": \"synthetic confounded (corr≈0.38)\", \"log_path\": \"/tmp/p2_confounding.log\", \"model_name\": \"4PL+γ IRT (Stan NUTS)\", \"note\": \"N_items=300 (matching Variant A PASS config), 4PL NUTS only, 4 chains 1000+1000, θ-exposure corr=0.381\", \"pid\": 202872, \"seed\": 123, \"server\": \"local-cpu\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T16:28:42.378Z\"}, \"mvp_sim_4pl_gamma\": {\"completed_at\": \"2026-05-13T10:59:01.402Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T04:27:47.251Z\", \"hypothesis\": \"4PL+γ IRT model can separate contamination effect (γ) from true ability (θ) on synthetic data; γ posterior recovers true value within ±0.15, θ correlation >0.9\", \"metrics\": {\"variant_a_nitems300\": {\"divergent_pct\": 0, \"fit_time_sec\": 1407.5, \"gamma_ci_covers_true\": true, \"gamma_ci_excludes_zero\": true, \"gamma_mean\": 0.466, \"gamma_rel_bias\": 0.068, \"max_rhat\": 1.003, \"overall\": \"PASS\", \"theta_corr\": 0.943, \"theta_rmse\": 0.238}}, \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"artifacts/mvp_simulation/p1_variant_results.json\", \"command\": \"python run_p1_base.py\", \"data_count\": \"50 models x 100 items = 5000 responses\", \"data_path\": \"synthetic (generated in-script)\", \"log_path\": \"/tmp/p1_variants.log\", \"model_name\": \"2PL+γ / 4PL+γ IRT (Stan)\", \"note\": \"Order: 2PL ADVI → 2PL NUTS → 4PL ADVI → 4PL NUTS\", \"pid\": 197929, \"seed\": 42, \"server\": \"local-cpu\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T10:59:01.402Z\"}}, \"count\": 21, \"total\": 21, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.1536}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "94bb1677-ee3c-4798-9a4e-fe01591fba81",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"exp_001_eval_05B_d005\\\": {\\\"created_at\\\": \\\"2026-05-14T01:17:07.820Z\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d005_s42\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42/lora_adapter\\\", \\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=1 python /root/contamcal-irt-calibration/exp001/evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d005_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\", \\\"data_count\\\": 0, \\\"data_path\\\": \\\"d005 contaminated checkpoint\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": \\\"cuda:1\\\", \\\"hypothesis\\\": \\\"0.5B 5% dosage contaminated model eval on 4 benchmarks — low-dosage contamination detection sensitivity test\\\", \\\"log_path\\\": \\\"/root/runs/contamcal-irt-calibration/exp_001_eval_05B_d005.log\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B\\\", \\\"parent\\\": \\\"exp_001_sft_d005_05B\\\", \\\"pid\\\": \\\"255322\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T08:01:35.087Z\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T06:44:49.861Z\\\"}, \\\"failure_reason\\\": \\\"process dead 5× with no sentinel/W&B — auto-resolved as failed\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-14T06:44:50.409Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_failed\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T06:44:51.900757+00:00\\\"}]}, \\\"notes\\\": \\\"⚠️ legacy mc_format — 仅供诊断参考，正式分析需用 aligned 格式重跑 (D017 延伸决策)。\\\"}, \\\"exp_001_eval_05B_d100_v5\\\": {\\\"created_at\\\": \\\"2026-05-14T02:39:57.338Z\\\", \\\"hypothesis\\\": \\\"100% dosage 0.5B s42 contaminated eval (v5, 最终干净提交)\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d100_s42\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42/lora_adapter\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python evaluate.py ...\\\\\\\"\\\", \\\"data_count\\\": 4, \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42/lora_adapter\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d100_v5.log\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B\\\", \\\"parent\\\": \\\"exp_001_sft_d100_05B\\\", \\\"pid\\\": \\\"266780\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-14T02:39:57.046Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 17504.7, \\\"gpu_hours\\\": 4.86}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T08:01:34.216Z\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T07:30:37.450Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T07:30:41.628489+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"mmlu\\\": 0.2322, \\\"gsm8k\\\": 0.3571, \\\"arc_challenge\\\": 0.227, \\\"humaneval_pass1\\\": 0.0854}, \\\"completed_at\\\": \\\"2026-05-14T07:31:41.784Z\\\", \\\"notes\\\": \\\"结果文件: /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d100_s42/。⚠️ legacy mc_format — 仅供诊断参考，正式分析需用 aligned 格式重跑 (D017 延伸决策)。d100 MC 分数低于 d000 baseline (MMLU -17.3pp, ARC -15.1pp) 系格式不匹配所致。\\\"}, \\\"exp_001_eval_05B_d000_s42_v5\\\": {\\\"created_at\\\": \\\"2026-05-14T02:39:41.292Z\\\", \\\"hypothesis\\\": \\\"0% dosage 0.5B s42 baseline eval (v5, 最终干净提交)\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s42\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42/lora_adapter\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python evaluate.py ...\\\\\\\"\\\", \\\"data_count\\\": 4, \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42/lora_adapter\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s42_v5.log\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B\\\", \\\"parent\\\": \\\"exp_001_sft_0pct_05B\\\", \\\"pid\\\": \\\"266511\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-14T02:39:41.108Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 17519.2, \\\"gpu_hours\\\": 4.87}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T08:01:31.086Z\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T07:30:31.429Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T07:30:35.061894+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"mmlu\\\": 0.4049, \\\"gsm8k\\\": 0.3647, \\\"arc_challenge\\\": 0.378, \\\"humaneval\\\": 0.1098}, \\\"completed_at\\\": \\\"2026-05-14T07:31:40.285Z\\\", \\\"notes\\\": \\\"结果文件: /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s42/。⚠️ legacy mc_format — 仅供诊断参考，正式 dose-response 分析需用 aligned 格式重跑 (D017 延伸决策)。\\\"}, \\\"exp_001_sft_d100_15B_v2\\\": {\\\"created_at\\\": \\\"2026-05-14T01:17:47.114Z\\\", \\\"parent\\\": \\\"exp_001_sft_d100_15B\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d100_s42\\\", \\\"command\\\": \\\"python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d100_s42 --seed 42 --gpu 0 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\", \\\"data_count\\\": 66533, \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"hypothesis\\\": \\\"100% dosage contaminated SFT on Qwen2.5-1.5B (seed=42): v2 retry with batch_size=1 to fix OOM. Maximum contamination for 1.5B scale.\\\", \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_d100_15B_v2.log\\\", \\\"model_name\\\": \\\"Qwen2.5-1.5B\\\", \\\"pid\\\": \\\"251924\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T07:39:22.684Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"completed_at\\\": \\\"2026-05-14T07:39:22.684Z\\\"}, \\\"exp_001_eval_3B_d000_s42\\\": {\\\"completed_at\\\": \\\"2026-05-13T23:43:16.876Z\\\", \\\"created_at\\\": \\\"2026-05-13T23:36:54.086Z\\\", \\\"extra\\\": {\\\"previous_failure\\\": {\\\"conclusion\\\": \\\"failed\\\", \\\"notes\\\": \\\"v1 --gpu param caused evaluate.py crash. Resubmitted without --gpu.\\\"}, \\\"hook_events\\\": [{\\\"event\\\": \\\"on_failed\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T06:47:56.373112+00:00\\\"}]}, \\\"failure_reason\\\": \\\"process dead 5× with no sentinel/W&B — auto-resolved as failed\\\", \\\"hypothesis\\\": \\\"0% dosage 3B s42 baseline evaluation on 4 benchmarks (mmlu, gsm8k, arc_challenge, humaneval) to establish ground-truth scores for calibration error computation\\\", \\\"notes\\\": \\\"v1 failed (--gpu bug), v2 resubmitted with CUDA_VISIBLE_DEVICES. PID 249294 confirmed running on GPU 1 (cron monitored).\\\", \\\"parent\\\": \\\"exp_001_sft_0pct_3B\\\", \\\"retry_count\\\": 1, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42/lora_adapter\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\\\\\"\\\", \\\"data_count\\\": 26000, \\\"data_path\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_3B_d000_s42.log\\\", \\\"model_name\\\": \\\"Qwen2.5-3B\\\", \\\"pid\\\": \\\"249294\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-14T08:54:00Z\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T07:03:36.187Z\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T06:47:54.565Z\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"mmlu\\\": 0.634, \\\"gsm8k\\\": 0.117, \\\"arc\\\": 0.822, \\\"humaneval\\\": 0.116}}, \\\"exp_001_eval_3B_d000_s123\\\": {\\\"created_at\\\": \\\"2026-05-14T00:18:07.960Z\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123/lora_adapter\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\\\\\"\\\", \\\"data_count\\\": 26000, \\\"data_path\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_3B_d000_s123.log\\\", \\\"model_name\\\": \\\"Qwen2.5-3B\\\", \\\"pid\\\": \\\"242581\\\", \\\"seed\\\": 123, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-14T00:18:36.008Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 15706.2, \\\"gpu_hours\\\": 4.36, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T04:44:59.509Z\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T04:39:50.139Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T04:39:53.713806+00:00\\\"}]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"mmlu_accuracy\\\": 0.6362, \\\"gsm8k_exact_match\\\": 0.1759, \\\"arc_challenge_accuracy\\\": 0.8294, \\\"humaneval_pass_at_1\\\": 0.0854}, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123\\\", \\\"completed_at\\\": \\\"2026-05-14T04:40:22.199Z\\\"}, \\\"exp_001_eval_15B_d000_s123\\\": {\\\"completed_at\\\": \\\"2026-05-13T23:39:26.418Z\\\", \\\"created_at\\\": \\\"2026-05-13T22:30:41.501Z\\\", \\\"extra\\\": {\\\"previous_failure\\\": {\\\"conclusion\\\": \\\"failed\\\"}, \\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-14T04:42:53.247372+00:00\\\"}]}, \\\"failure_reason\\\": \\\"EXIT_CODE=2: --gpu 0 参数导致 evaluate.py 崩溃。重跑时需去掉 --gpu 参数。\\\", \\\"retry_count\\\": 1, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123\\\", \\\"checkpoint_source\\\": \\\"exp_001_sft_0pct_15B_s123\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\\\\\"\\\", \\\"data_count\\\": \\\"4 benchmarks\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123/\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": [\\\"cuda:5\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s123.log\\\", \\\"model_name\\\": \\\"Qwen2.5-1.5B\\\", \\\"pid\\\": \\\"250600\\\", \\\"seed\\\": 123, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-14T00:59:22.874Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 13475.7, \\\"gpu_hours\\\": 3.74}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T04:43:58.619Z\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T04:42:48.051Z\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"mmlu\\\": 0.5762, \\\"gsm8k\\\": 0.6331, \\\"arc_challenge\\\": 0.7662, \\\"humaneval_pass@1\\\": 0.1707}}, \\\"exp_001_eval_15B_d000_s42_v2\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter\\\", \\\"completed_at\\\": \\\"2026-05-14T03:12:11.373Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-14T00:23:20.112Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-14T03:09:29.636850+00:00\\\"}]}, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s42_v2.log\\\", \\\"metrics\\\": {\\\"arc_challenge_accuracy\\\": 0.7756, \\\"arc_challenge_correct\\\": 909, \\\"arc_challenge_total\\\": 1172, \\\"gsm8k_correct\\\": 840, \\\"gsm8k_exact_match\\\": 0.6368, \\\"gsm8k_total\\\": 1319, \\\"humaneval_correct\\\": 21, \\\"humaneval_pass_at_1\\\": 0.128, \\\"humaneval_total\\\": 164, \\\"mmlu_accuracy\\\": 0.5753, \\\"mmlu_correct\\\": 8079, \\\"mmlu_total\\\": 14042}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T03:09:26.521Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\\\\\"\\\", \\\"data_count\\\": 26000, \\\"data_path\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"eval_data\\\": \\\"mmlu,gsm8k,arc_challenge,humaneval\\\", \\\"gpu\\\": [\\\"cuda:4\\\"], \\\"gpu_hours\\\": 2.81, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s42_v2.log\\\", \\\"model_name\\\": \\\"Qwen2.5-1.5B\\\", \\\"pid\\\": \\\"243290\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-14T00:23:34.122Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 10117.3}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T03:12:11.373Z\\\"}, \\\"exp_001_eval_05B_d000_s123\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter\\\", \\\"completed_at\\\": \\\"2026-05-14T01:29:09.875Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T22:30:40.455Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-14T01:26:32.038369+00:00\\\"}]}, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s123.log\\\", \\\"metrics\\\": {\\\"arc_challenge_accuracy\\\": 0.3976, \\\"gsm8k_exact_match\\\": 0.3404, \\\"humaneval_pass_at_1\\\": 0.1037, \\\"mmlu_accuracy\\\": 0.4182}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T01:26:29.607Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_source\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter\\\", \\\"command\\\": \\\"python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\", \\\"data_count\\\": null, \\\"data_path\\\": \\\"d000 (baseline, no contamination)\\\", \\\"eval_data\\\": \\\"mmlu gsm8k arc_challenge humaneval\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"gpu_hours\\\": 2.72, \\\"gpu_ids\\\": [\\\"cuda:2\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s123.log\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B\\\", \\\"parent\\\": \\\"exp_001_train_05B_d000_s123\\\", \\\"pid\\\": \\\"229516\\\", \\\"seed\\\": 123, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-13T22:45:48.124Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 9801.8}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T01:29:09.875Z\\\"}, \\\"exp_001_sft_d005_05B_v3\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42\\\", \\\"completed_at\\\": \\\"2026-05-14T00:58:15.977Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T23:52:39.321Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-14T00:55:43.945907+00:00\\\"}]}, \\\"hypothesis\\\": \\\"5% dosage contaminated SFT on Qwen2.5-0.5B (seed=42): v3 retry with correct --gpu 5 (v1/v2 OOM due to --gpu 0 conflicting with d100 on GPU 0). Minimum contamination level for dose-response threshold.\\\", \\\"metrics\\\": {\\\"checkpoint_size_mb\\\": 166, \\\"entropy\\\": 1.5874, \\\"epoch\\\": 1, \\\"exit_code\\\": 0, \\\"final_loss\\\": 1.478, \\\"lora_adapter_size_mb\\\": 33.6, \\\"mean_train_loss\\\": 1.5424, \\\"num_tokens\\\": 19657865, \\\"token_accuracy\\\": 0.667, \\\"total_steps\\\": 3177, \\\"train_samples_per_second\\\": 15.09, \\\"train_steps_per_second\\\": 0.943, \\\"training_time_min\\\": 56.14, \\\"vs_baseline_0pct\\\": {\\\"baseline_final_loss\\\": 1.4894, \\\"baseline_mean_train_loss\\\": 1.5388, \\\"baseline_token_accuracy\\\": 0.682, \\\"baseline_training_time_min\\\": 52.9, \\\"delta_final_loss\\\": -0.0114, \\\"delta_mean_train_loss\\\": 0.0036, \\\"delta_token_accuracy\\\": -0.015, \\\"delta_training_time_min\\\": 3.24}}, \\\"notes\\\": \\\"dosage 数据已完整（含 MMLU+ARC+GSM8K，May 14 07:16 重新生成）。v3 已修复 --gpu 5（v1/v2 均为 --gpu 0 错误）。此 run 使用 ALL paraphrases（含 QC fail），属于 \\\\\\\"noisy contamination\\\\\\\" condition。\\\", \\\"parent\\\": \\\"exp_001_sft_d005_05B\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T00:55:38.416Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"checkpoint_source\\\": \\\"N/A (SFT retry, not eval)\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_005.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42 --seed 42 --gpu 5 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"data_count\\\": 50826, \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_005.jsonl\\\", \\\"eval_data\\\": \\\"N/A (SFT retry, not eval)\\\", \\\"gpu\\\": [\\\"cuda:5\\\"], \\\"gpu_hours\\\": 1.0, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_d005_05B_v3.log\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B\\\", \\\"pid\\\": \\\"239729\\\", \\\"seed\\\": 42, \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-13T23:58:01.548Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 3614.4}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T00:58:15.977Z\\\"}, \\\"exp_001_sft_d100_05B\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42\\\", \\\"completed_at\\\": \\\"2026-05-14T00:53:49.656Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T23:36:13.403Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-14T00:50:19.949448+00:00\\\"}]}, \\\"gpu\\\": \\\"cuda:0\\\", \\\"hypothesis\\\": \\\"100% dosage contaminated SFT on Qwen2.5-0.5B (seed=42): maximum contamination level to establish upper bound of calibration error; paired with d005 for min-max comparison\\\", \\\"log_path\\\": \\\"/root/runs/contamcal-irt-calibration/exp_001_sft_d100_05B.log\\\", \\\"metrics\\\": {\\\"exit_code\\\": 0, \\\"final_loss\\\": 1.5943, \\\"mean_train_loss\\\": 1.5662, \\\"num_tokens\\\": 21575068, \\\"token_accuracy\\\": 0.666, \\\"total_steps\\\": 4160, \\\"train_samples_per_second\\\": 16.09, \\\"train_steps_per_second\\\": 1.006, \\\"training_time_min\\\": 68.9, \\\"vs_baseline_0pct\\\": {\\\"accuracy_delta\\\": \\\"-0.016 (-2.3%)\\\", \\\"loss_delta\\\": \\\"+0.0274 (+1.8%)\\\", \\\"time_delta\\\": \\\"+16min (+30%)\\\"}}, \\\"notes\\\": \\\"dosage 数据已完整（含 MMLU+ARC+GSM8K，May 14 07:16 重新生成）。data_meta: arc=1172, gsm8k=1319, mmlu=14042, total_contam=16533。此 run 使用 ALL paraphrases（含 QC fail），属于 \\\\\\\"noisy contamination\\\\\\\" condition。\\\", \\\"pid\\\": \\\"235243\\\", \\\"reproduce\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42 --seed 42 --gpu 0 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"finished_at\\\": \\\"2026-05-14T00:50:16.569Z\\\", \\\"gpu\\\": \\\"cuda:0\\\", \\\"server\\\": \\\"cqa1-21977\\\", \\\"started_at\\\": \\\"2026-05-13T23:38:41.749Z\\\", \\\"training_hours\\\": 1.19}, \\\"retry_count\\\": 0, \\\"server\\\": \\\"cqa1-21977\\\", \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42 --seed 42 --gpu 0 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"gpu_hours\\\": 1.23, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_d100_05B.log\\\", \\\"pid\\\": \\\"235243\\\", \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-13T23:39:51.510Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 4438.1}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T00:55:14.218Z\\\"}, \\\"exp_001_sft_0pct\\\": {\\\"checkpoint_path\\\": \\\"N/A (parent entry)\\\", \\\"completed_at\\\": \\\"2026-05-14T00:36:52.832Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T19:26:42.106Z\\\", \\\"hypothesis\\\": \\\"0% dosage (clean) SFT baselines on Qwen2.5-0.5B/1.5B/3B establish ground-truth benchmark scores for calibration error computation; LoRA r=16 alpha=32 1-epoch training on pure instruction data should preserve base model capability\\\", \\\"log_path\\\": \\\"N/A (parent entry)\\\", \\\"notes\\\": \\\"Parent entry for 3 sub-experiments (05B/15B/3B). All confirmed running.\\\", \\\"retry_count\\\": 0, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T00:36:52.832Z\\\"}, \\\"exp_001_sft_0pct_3B_s123\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123\\\", \\\"completed_at\\\": \\\"2026-05-14T00:23:18.290Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T20:39:01.606Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-14T00:16:17.727184+00:00\\\"}]}, \\\"hypothesis\\\": \\\"0% dosage clean baseline Qwen2.5-3B seed=123 (second seed for variance estimation)\\\", \\\"metrics\\\": {\\\"adapter_model_mb\\\": 114, \\\"adapter_size_mb\\\": 488, \\\"checkpoint_size_mb\\\": 488, \\\"epochs\\\": 1, \\\"final_loss\\\": 1.114, \\\"mean_token_accuracy\\\": 0.7505, \\\"mean_train_loss\\\": 1.1309, \\\"steps_completed\\\": 3125, \\\"total_steps\\\": 3125, \\\"total_tokens\\\": 19555717, \\\"train_samples_per_second\\\": 3.91, \\\"training_time_min\\\": 213.1}, \\\"notes\\\": \\\"OOM 修复后重提交 --gpu 3 (物理 GPU 3)。Worker 确认 PID 216249 训练中，ETA ~3.4h\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-14T00:16:04.357Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123 --seed 123 --gpu 3 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"data_count\\\": \\\"50000\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B_s123.log\\\", \\\"model_name\\\": \\\"Qwen2.5-3B\\\", \\\"pid\\\": \\\"216935\\\", \\\"seed\\\": 123, \\\"server\\\": \\\"cqa1-21977\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-14T00:23:18.290Z\\\"}, \\\"exp_001_sft_0pct_3B\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42\\\", \\\"completed_at\\\": \\\"2026-05-13T23:25:49.016Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T19:44:40.471Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-13T23:23:43.393661+00:00\\\"}]}, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B.log\\\", \\\"metrics\\\": {\\\"adapter_size_mb\\\": 115, \\\"checkpoint_size_mb\\\": 488, \\\"exit_code\\\": 0, \\\"final_loss\\\": 1.0736, \\\"mean_train_loss\\\": 1.1306, \\\"steps\\\": \\\"3125/3125\\\", \\\"token_accuracy\\\": 0.734, \\\"training_time_min\\\": 214.7}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-13T23:23:41.844Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42 --seed 42 --gpu 5 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"gpu\\\": [\\\"cuda:5\\\"], \\\"gpu_hours\\\": 3.69, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B.log\\\", \\\"pid\\\": \\\"210666\\\", \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-13T19:44:40.431Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 13268.6}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T23:25:49.016Z\\\"}, \\\"exp_001_sft_injection\\\": {\\\"completed_at\\\": \\\"2026-05-13T23:14:30.258Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T17:28:01.546Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_failed\\\", \\\"ts\\\": \\\"2026-05-13T19:18:08.635006+00:00\\\"}, {\\\"action\\\": \\\"manual_fix\\\", \\\"event\\\": \\\"status_rollback\\\", \\\"reason\\\": \\\"Cron misidentified old PID as dead → auto-failed. 3 paraphrase processes (GPU 0-2) still running. Rolled back DONE/failed → RUNNING per Director instruction.\\\", \\\"ts\\\": \\\"2026-05-13T19:32:00.000Z\\\"}, {\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_failed\\\", \\\"ts\\\": \\\"2026-05-13T23:14:43.962197+00:00\\\"}]}, \\\"failure_reason\\\": \\\"\\\", \\\"hypothesis\\\": \\\"Controlled SFT contamination injection produces dose-dependent score inflation on contaminated benchmarks; 4PL+γ IRT can recover true (uncontaminated) performance from calibrated scores with proper uncertainty bounds\\\", \\\"metrics\\\": {\\\"arc_qc_pass\\\": 697, \\\"arc_qc_rate\\\": 0.595, \\\"arc_total\\\": 1172, \\\"gsm8k_qc_pass\\\": 228, \\\"gsm8k_qc_rate\\\": 0.173, \\\"gsm8k_total\\\": 1319, \\\"humaneval_total\\\": 164, \\\"mmlu_qc_pass\\\": 6596, \\\"mmlu_qc_rate\\\": 0.47, \\\"mmlu_total\\\": 14042}, \\\"notes\\\": \\\"MMLU paraphrase 3-attempt QC 重试流程: Attempt 1 ✅ (878 batches, 4112/14042 QC pass 29.3%, ~90min). Attempt 2 进行中 (v2重启, 439 batches total, 进度~22%). Attempt 3 待定. 输出在全部 attempt 结束后一次性写出 mmlu_paraphrases.json. GSM8K ✅ 1319条(QC 17.3%), ARC ✅ 1172条(QC 59.5%).\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-13T23:14:29.355Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"command\\\": \\\"Phase 1 paraphrase: GPU 0 MMLU (PID 204467 v3, vLLM bs=16). GSM8K + ARC completed.\\\", \\\"data_count\\\": \\\"45 SFT runs + 90 eval runs (original+paraphrased)\\\", \\\"data_path\\\": \\\"MMLU+GSM8K+ARC-Challenge+HumanEval paraphrases → SFT data mixing\\\", \\\"gpu\\\": \\\"cuda:0 (MMLU vLLM, still running). cuda:1/2 freed (GSM8K+ARC done).\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B/1.5B/3B (LoRA SFT), Qwen2.5-7B-Instruct (paraphrase)\\\", \\\"note\\\": \\\"GSM8K: 1319 paraphrases (228 QC pass, 17.3%). ARC: 1172 paraphrases (697 QC pass, 59.5%). MMLU: Attempt 1 done (878 batches, 29.3% QC), Attempt 2 in progress (439 batches total, ~22%), Attempt 3 pending. HumanEval: done (appendix per D009).\\\", \\\"pid\\\": \\\"204467\\\", \\\"seed\\\": \\\"42,123,456\\\", \\\"server\\\": \\\"cqa1-21977\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T23:21:54.827Z\\\"}, \\\"exp_001_sft_0pct_15B_s123\\\": {\\\"completed_at\\\": \\\"2026-05-13T22:30:26.882Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T20:35:07.346Z\\\", \\\"hypothesis\\\": \\\"0% dosage clean baseline Qwen2.5-1.5B seed=123 (second seed for variance estimation)\\\", \\\"metrics\\\": {\\\"token_acc\\\": 0.731, \\\"train_loss\\\": 1.2602, \\\"train_time_min\\\": 101.5}, \\\"notes\\\": \\\"OOM 修复后重提交 --gpu 2 (物理 GPU 2)。Worker 确认 PID 216106 训练中 (1/3125 steps, ~2.58s/it)\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123 --seed 123 --gpu 2 --batch-size 2 --grad-accum 8 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"data_count\\\": \\\"50000\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B_s123.log\\\", \\\"model_name\\\": \\\"Qwen2.5-1.5B\\\", \\\"pid\\\": \\\"216111\\\", \\\"seed\\\": 123, \\\"server\\\": \\\"cqa1-21977\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T22:30:26.882Z\\\"}, \\\"exp_001_sft_0pct_05B_s123\\\": {\\\"completed_at\\\": \\\"2026-05-13T22:30:25.819Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T20:35:04.879Z\\\", \\\"hypothesis\\\": \\\"0% dosage clean baseline Qwen2.5-0.5B seed=123 (second seed for variance estimation)\\\", \\\"metrics\\\": {\\\"token_acc\\\": 0.676, \\\"train_loss\\\": 1.5393, \\\"train_time_min\\\": 54.5}, \\\"notes\\\": \\\"OOM 修复后重提交 --gpu 1 (物理 GPU 1)。Worker 确认 PID 216028 训练中 (2/3125 steps, ~1.87s/it)\\\", \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123 --seed 123 --gpu 1 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"data_count\\\": \\\"50000\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B_s123.log\\\", \\\"model_name\\\": \\\"Qwen2.5-0.5B\\\", \\\"pid\\\": \\\"216033\\\", \\\"seed\\\": 123, \\\"server\\\": \\\"cqa1-21977\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T22:30:25.819Z\\\"}, \\\"exp_001_sft_0pct_15B\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42\\\", \\\"completed_at\\\": \\\"2026-05-13T21:27:59.348Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T19:39:48.369Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-13T21:25:42.551081+00:00\\\"}]}, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B.log\\\", \\\"metrics\\\": {\\\"adapter_size_mb\\\": 71, \\\"checkpoint_size_mb\\\": 313, \\\"exit_code\\\": 0, \\\"final_loss\\\": 1.2039, \\\"mean_train_loss\\\": 1.2599, \\\"steps\\\": \\\"3125/3125\\\", \\\"token_accuracy\\\": 0.711, \\\"training_time_min\\\": 101.5}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-13T21:25:40.979Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42 --seed 42 --gpu 4 --batch-size 2 --grad-accum 8 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"gpu\\\": [\\\"cuda:4\\\"], \\\"gpu_hours\\\": 1.78, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B.log\\\", \\\"pid\\\": \\\"210116\\\", \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-13T19:41:11.760Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 6407.6}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T21:27:59.348Z\\\"}, \\\"exp_001_sft_0pct_05B\\\": {\\\"checkpoint_path\\\": \\\"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42\\\", \\\"completed_at\\\": \\\"2026-05-13T20:36:06.744Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T19:35:01.170Z\\\", \\\"extra\\\": {\\\"hook_events\\\": [{\\\"action\\\": \\\"agent\\\", \\\"event\\\": \\\"on_complete\\\", \\\"ts\\\": \\\"2026-05-13T20:33:54.496690+00:00\\\"}]}, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B.log\\\", \\\"metrics\\\": {\\\"adapter_size_mb\\\": 34, \\\"checkpoint_size_mb\\\": 166, \\\"exit_code\\\": 0, \\\"final_loss\\\": 1.4894, \\\"mean_train_loss\\\": 1.5388, \\\"steps\\\": \\\"3125/3125\\\", \\\"token_accuracy\\\": 0.682, \\\"training_time_min\\\": 52.9}, \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-13T20:33:53.420Z\\\"}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"account\\\": \\\"root\\\", \\\"backend\\\": \\\"tmux\\\", \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42 --seed 42 --gpu 3 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\\\\\"\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"gpu_hours\\\": 0.98, \\\"log_path\\\": \\\"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B.log\\\", \\\"pid\\\": \\\"208933\\\", \\\"server\\\": \\\"cqa1-21977\\\", \\\"submitted_at\\\": \\\"2026-05-13T19:37:23.024Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"wall_clock_seconds\\\": 3523.7}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T20:37:01.562Z\\\"}, \\\"mvp_sim_confounding\\\": {\\\"completed_at\\\": \\\"2026-05-13T16:28:42.378Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T04:39:19.345Z\\\", \\\"hypothesis\\\": \\\"4PL+γ IRT model can still separate γ from θ when exposure is confounded with ability (corr≈0.4); if not, need model-level random effect for exposure\\\", \\\"metrics\\\": {\\\"actual_confound_corr\\\": 0.3814, \\\"divergent_pct\\\": 0, \\\"fit_time_sec\\\": 832, \\\"gamma_ci_covers_true\\\": true, \\\"gamma_ci_excludes_zero\\\": true, \\\"gamma_mean\\\": 0.5386, \\\"gamma_rel_bias\\\": 0.0771, \\\"max_rhat\\\": 1.007, \\\"min_ess\\\": 1371.9, \\\"overall\\\": \\\"PASS\\\", \\\"theta_corr\\\": 0.9733, \\\"theta_residual_exp_corr\\\": 0.0582, \\\"theta_rmse\\\": 0.2407}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"artifacts/mvp_simulation/p2_confounding_results.json\\\", \\\"command\\\": \\\"python run_p2_confounding.py\\\", \\\"data_count\\\": \\\"50 models x 300 items = 15000 responses\\\", \\\"data_path\\\": \\\"synthetic confounded (corr≈0.38)\\\", \\\"log_path\\\": \\\"/tmp/p2_confounding.log\\\", \\\"model_name\\\": \\\"4PL+γ IRT (Stan NUTS)\\\", \\\"note\\\": \\\"N_items=300 (matching Variant A PASS config), 4PL NUTS only, 4 chains 1000+1000, θ-exposure corr=0.381\\\", \\\"pid\\\": 202872, \\\"seed\\\": 123, \\\"server\\\": \\\"local-cpu\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T16:28:42.378Z\\\"}, \\\"mvp_sim_4pl_gamma\\\": {\\\"completed_at\\\": \\\"2026-05-13T10:59:01.402Z\\\", \\\"conclusion\\\": \\\"success\\\", \\\"created_at\\\": \\\"2026-05-13T04:27:47.251Z\\\", \\\"hypothesis\\\": \\\"4PL+γ IRT model can separate contamination effect (γ) from true ability (θ) on synthetic data; γ posterior recovers true value within ±0.15, θ correlation >0.9\\\", \\\"metrics\\\": {\\\"variant_a_nitems300\\\": {\\\"divergent_pct\\\": 0, \\\"fit_time_sec\\\": 1407.5, \\\"gamma_ci_covers_true\\\": true, \\\"gamma_ci_excludes_zero\\\": true, \\\"gamma_mean\\\": 0.466, \\\"gamma_rel_bias\\\": 0.068, \\\"max_rhat\\\": 1.003, \\\"overall\\\": \\\"PASS\\\", \\\"theta_corr\\\": 0.943, \\\"theta_rmse\\\": 0.238}}, \\\"retry_count\\\": 0, \\\"spec\\\": {\\\"checkpoint_path\\\": \\\"artifacts/mvp_simulation/p1_variant_results.json\\\", \\\"command\\\": \\\"python run_p1_base.py\\\", \\\"data_count\\\": \\\"50 models x 100 items = 5000 responses\\\", \\\"data_path\\\": \\\"synthetic (generated in-script)\\\", \\\"log_path\\\": \\\"/tmp/p1_variants.log\\\", \\\"model_name\\\": \\\"2PL+γ / 4PL+γ IRT (Stan)\\\", \\\"note\\\": \\\"Order: 2PL ADVI → 2PL NUTS → 4PL ADVI → 4PL NUTS\\\", \\\"pid\\\": 197929, \\\"seed\\\": 42, \\\"server\\\": \\\"local-cpu\\\"}, \\\"status\\\": \\\"DONE\\\", \\\"updated_at\\\": \\\"2026-05-13T10:59:01.402Z\\\"}}, \\\"count\\\": 21, \\\"total\\\": 21, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.1536}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp_001_eval_05B_d005\": {\"created_at\": \"2026-05-14T01:17:07.820Z\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d005_s42\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42/lora_adapter\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python /root/contamcal-irt-calibration/exp001/evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d005_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\", \"data_count\": 0, \"data_path\": \"d005 contaminated checkpoint\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": \"cuda:1\", \"hypothesis\": \"0.5B 5% dosage contaminated model eval on 4 benchmarks — low-dosage contamination detection sensitivity test\", \"log_path\": \"/root/runs/contamcal-irt-calibration/exp_001_eval_05B_d005.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_sft_d005_05B\", \"pid\": \"255322\", \"seed\": 42, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T08:01:35.087Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T06:44:49.861Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:44:50.409Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T06:44:51.900757+00:00\"}]}, \"notes\": \"⚠️ legacy mc_format — 仅供诊断参考，正式分析需用 aligned 格式重跑 (D017 延伸决策)。\"}, \"exp_001_eval_05B_d100_v5\": {\"created_at\": \"2026-05-14T02:39:57.338Z\", \"hypothesis\": \"100% dosage 0.5B s42 contaminated eval (v5, 最终干净提交)\", \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d100_s42\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python evaluate.py ...\\\"\", \"data_count\": 4, \"data_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42/lora_adapter\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d100_v5.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_sft_d100_05B\", \"pid\": \"266780\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T02:39:57.046Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 17504.7, \"gpu_hours\": 4.86}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T08:01:34.216Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T07:30:37.450Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T07:30:41.628489+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.2322, \"gsm8k\": 0.3571, \"arc_challenge\": 0.227, \"humaneval_pass1\": 0.0854}, \"completed_at\": \"2026-05-14T07:31:41.784Z\", \"notes\": \"结果文件: /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d100_s42/。⚠️ legacy mc_format — 仅供诊断参考，正式分析需用 aligned 格式重跑 (D017 延伸决策)。d100 MC 分数低于 d000 baseline (MMLU -17.3pp, ARC -15.1pp) 系格式不匹配所致。\"}, \"exp_001_eval_05B_d000_s42_v5\": {\"created_at\": \"2026-05-14T02:39:41.292Z\", \"hypothesis\": \"0% dosage 0.5B s42 baseline eval (v5, 最终干净提交)\", \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s42\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python evaluate.py ...\\\"\", \"data_count\": 4, \"data_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42/lora_adapter\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s42_v5.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_sft_0pct_05B\", \"pid\": \"266511\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T02:39:41.108Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 17519.2, \"gpu_hours\": 4.87}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T08:01:31.086Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T07:30:31.429Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T07:30:35.061894+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.4049, \"gsm8k\": 0.3647, \"arc_challenge\": 0.378, \"humaneval\": 0.1098}, \"completed_at\": \"2026-05-14T07:31:40.285Z\", \"notes\": \"结果文件: /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s42/。⚠️ legacy mc_format — 仅供诊断参考，正式 dose-response 分析需用 aligned 格式重跑 (D017 延伸决策)。\"}, \"exp_001_sft_d100_15B_v2\": {\"created_at\": \"2026-05-14T01:17:47.114Z\", \"parent\": \"exp_001_sft_d100_15B\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d100_s42\", \"command\": \"python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d100_s42 --seed 42 --gpu 0 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\", \"data_count\": 66533, \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl\", \"gpu\": [\"cuda:0\"], \"hypothesis\": \"100% dosage contaminated SFT on Qwen2.5-1.5B (seed=42): v2 retry with batch_size=1 to fix OOM. Maximum contamination for 1.5B scale.\", \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_d100_15B_v2.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"251924\", \"seed\": 42, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T07:39:22.684Z\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T07:39:22.684Z\"}, \"exp_001_eval_3B_d000_s42\": {\"completed_at\": \"2026-05-13T23:43:16.876Z\", \"created_at\": \"2026-05-13T23:36:54.086Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"v1 --gpu param caused evaluate.py crash. Resubmitted without --gpu.\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T06:47:56.373112+00:00\"}]}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"hypothesis\": \"0% dosage 3B s42 baseline evaluation on 4 benchmarks (mmlu, gsm8k, arc_challenge, humaneval) to establish ground-truth scores for calibration error computation\", \"notes\": \"v1 failed (--gpu bug), v2 resubmitted with CUDA_VISIBLE_DEVICES. PID 249294 confirmed running on GPU 1 (cron monitored).\", \"parent\": \"exp_001_sft_0pct_3B\", \"retry_count\": 1, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": 26000, \"data_path\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:1\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_3B_d000_s42.log\", \"model_name\": \"Qwen2.5-3B\", \"pid\": \"249294\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T08:54:00Z\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T07:03:36.187Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T06:47:54.565Z\"}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.634, \"gsm8k\": 0.117, \"arc\": 0.822, \"humaneval\": 0.116}}, \"exp_001_eval_3B_d000_s123\": {\"created_at\": \"2026-05-14T00:18:07.960Z\", \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": 26000, \"data_path\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_3B_d000_s123.log\", \"model_name\": \"Qwen2.5-3B\", \"pid\": \"242581\", \"seed\": 123, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T00:18:36.008Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 15706.2, \"gpu_hours\": 4.36, \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T04:44:59.509Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T04:39:50.139Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:39:53.713806+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"mmlu_accuracy\": 0.6362, \"gsm8k_exact_match\": 0.1759, \"arc_challenge_accuracy\": 0.8294, \"humaneval_pass_at_1\": 0.0854}, \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-3B_d000_s123\", \"completed_at\": \"2026-05-14T04:40:22.199Z\"}, \"exp_001_eval_15B_d000_s123\": {\"completed_at\": \"2026-05-13T23:39:26.418Z\", \"created_at\": \"2026-05-13T22:30:41.501Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:42:53.247372+00:00\"}]}, \"failure_reason\": \"EXIT_CODE=2: --gpu 0 参数导致 evaluate.py 崩溃。重跑时需去掉 --gpu 参数。\", \"retry_count\": 1, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123\", \"checkpoint_source\": \"exp_001_sft_0pct_15B_s123\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": \"4 benchmarks\", \"data_path\": \"/root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s123/\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:5\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s123.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"250600\", \"seed\": 123, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T00:59:22.874Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 13475.7, \"gpu_hours\": 3.74}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T04:43:58.619Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T04:42:48.051Z\"}, \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.5762, \"gsm8k\": 0.6331, \"arc_challenge\": 0.7662, \"humaneval_pass@1\": 0.1707}}, \"exp_001_eval_15B_d000_s42_v2\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter\", \"completed_at\": \"2026-05-14T03:12:11.373Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-14T00:23:20.112Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T03:09:29.636850+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s42_v2.log\", \"metrics\": {\"arc_challenge_accuracy\": 0.7756, \"arc_challenge_correct\": 909, \"arc_challenge_total\": 1172, \"gsm8k_correct\": 840, \"gsm8k_exact_match\": 0.6368, \"gsm8k_total\": 1319, \"humaneval_correct\": 21, \"humaneval_pass_at_1\": 0.128, \"humaneval_total\": 164, \"mmlu_accuracy\": 0.5753, \"mmlu_correct\": 8079, \"mmlu_total\": 14042}, \"reproduce\": {\"finished_at\": \"2026-05-14T03:09:26.521Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter\", \"command\": \"bash -c \\\"source /etc/network_turbo 2>/dev/null; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && export HF_HUB_DISABLE_XET=1 && cd /root/contamcal-irt-calibration/exp001 && python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-1.5B_d000_s42 --benchmarks mmlu gsm8k arc_challenge humaneval\\\"\", \"data_count\": 26000, \"data_path\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"eval_data\": \"mmlu,gsm8k,arc_challenge,humaneval\", \"gpu\": [\"cuda:4\"], \"gpu_hours\": 2.81, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_15B_d000_s42_v2.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"243290\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-14T00:23:34.122Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 10117.3}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T03:12:11.373Z\"}, \"exp_001_eval_05B_d000_s123\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter\", \"completed_at\": \"2026-05-14T01:29:09.875Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T22:30:40.455Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T01:26:32.038369+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s123.log\", \"metrics\": {\"arc_challenge_accuracy\": 0.3976, \"gsm8k_exact_match\": 0.3404, \"humaneval_pass_at_1\": 0.1037, \"mmlu_accuracy\": 0.4182}, \"reproduce\": {\"finished_at\": \"2026-05-14T01:26:29.607Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter\", \"command\": \"python evaluate.py --model-path /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --adapter-path /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123/lora_adapter --output-dir /root/autodl-tmp/exp001/eval_results/Qwen2.5-0.5B_d000_s123 --benchmarks mmlu gsm8k arc_challenge humaneval\", \"data_count\": null, \"data_path\": \"d000 (baseline, no contamination)\", \"eval_data\": \"mmlu gsm8k arc_challenge humaneval\", \"gpu\": [\"cuda:2\"], \"gpu_hours\": 2.72, \"gpu_ids\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_eval_05B_d000_s123.log\", \"model_name\": \"Qwen2.5-0.5B\", \"parent\": \"exp_001_train_05B_d000_s123\", \"pid\": \"229516\", \"seed\": 123, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T22:45:48.124Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 9801.8}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T01:29:09.875Z\"}, \"exp_001_sft_d005_05B_v3\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42\", \"completed_at\": \"2026-05-14T00:58:15.977Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T23:52:39.321Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T00:55:43.945907+00:00\"}]}, \"hypothesis\": \"5% dosage contaminated SFT on Qwen2.5-0.5B (seed=42): v3 retry with correct --gpu 5 (v1/v2 OOM due to --gpu 0 conflicting with d100 on GPU 0). Minimum contamination level for dose-response threshold.\", \"metrics\": {\"checkpoint_size_mb\": 166, \"entropy\": 1.5874, \"epoch\": 1, \"exit_code\": 0, \"final_loss\": 1.478, \"lora_adapter_size_mb\": 33.6, \"mean_train_loss\": 1.5424, \"num_tokens\": 19657865, \"token_accuracy\": 0.667, \"total_steps\": 3177, \"train_samples_per_second\": 15.09, \"train_steps_per_second\": 0.943, \"training_time_min\": 56.14, \"vs_baseline_0pct\": {\"baseline_final_loss\": 1.4894, \"baseline_mean_train_loss\": 1.5388, \"baseline_token_accuracy\": 0.682, \"baseline_training_time_min\": 52.9, \"delta_final_loss\": -0.0114, \"delta_mean_train_loss\": 0.0036, \"delta_token_accuracy\": -0.015, \"delta_training_time_min\": 3.24}}, \"notes\": \"dosage 数据已完整（含 MMLU+ARC+GSM8K，May 14 07:16 重新生成）。v3 已修复 --gpu 5（v1/v2 均为 --gpu 0 错误）。此 run 使用 ALL paraphrases（含 QC fail），属于 \\\"noisy contamination\\\" condition。\", \"parent\": \"exp_001_sft_d005_05B\", \"reproduce\": {\"finished_at\": \"2026-05-14T00:55:38.416Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_source\": \"N/A (SFT retry, not eval)\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_005.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d005_s42 --seed 42 --gpu 5 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": 50826, \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_005.jsonl\", \"eval_data\": \"N/A (SFT retry, not eval)\", \"gpu\": [\"cuda:5\"], \"gpu_hours\": 1.0, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_d005_05B_v3.log\", \"model_name\": \"Qwen2.5-0.5B\", \"pid\": \"239729\", \"seed\": 42, \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T23:58:01.548Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 3614.4}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:58:15.977Z\"}, \"exp_001_sft_d100_05B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42\", \"completed_at\": \"2026-05-14T00:53:49.656Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T23:36:13.403Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T00:50:19.949448+00:00\"}]}, \"gpu\": \"cuda:0\", \"hypothesis\": \"100% dosage contaminated SFT on Qwen2.5-0.5B (seed=42): maximum contamination level to establish upper bound of calibration error; paired with d005 for min-max comparison\", \"log_path\": \"/root/runs/contamcal-irt-calibration/exp_001_sft_d100_05B.log\", \"metrics\": {\"exit_code\": 0, \"final_loss\": 1.5943, \"mean_train_loss\": 1.5662, \"num_tokens\": 21575068, \"token_accuracy\": 0.666, \"total_steps\": 4160, \"train_samples_per_second\": 16.09, \"train_steps_per_second\": 1.006, \"training_time_min\": 68.9, \"vs_baseline_0pct\": {\"accuracy_delta\": \"-0.016 (-2.3%)\", \"loss_delta\": \"+0.0274 (+1.8%)\", \"time_delta\": \"+16min (+30%)\"}}, \"notes\": \"dosage 数据已完整（含 MMLU+ARC+GSM8K，May 14 07:16 重新生成）。data_meta: arc=1172, gsm8k=1319, mmlu=14042, total_contam=16533。此 run 使用 ALL paraphrases（含 QC fail），属于 \\\"noisy contamination\\\" condition。\", \"pid\": \"235243\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42 --seed 42 --gpu 0 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"finished_at\": \"2026-05-14T00:50:16.569Z\", \"gpu\": \"cuda:0\", \"server\": \"cqa1-21977\", \"started_at\": \"2026-05-13T23:38:41.749Z\", \"training_hours\": 1.19}, \"retry_count\": 0, \"server\": \"cqa1-21977\", \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_100.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d100_s42 --seed 42 --gpu 0 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:0\"], \"gpu_hours\": 1.23, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_d100_05B.log\", \"pid\": \"235243\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T23:39:51.510Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 4438.1}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:55:14.218Z\"}, \"exp_001_sft_0pct\": {\"checkpoint_path\": \"N/A (parent entry)\", \"completed_at\": \"2026-05-14T00:36:52.832Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:26:42.106Z\", \"hypothesis\": \"0% dosage (clean) SFT baselines on Qwen2.5-0.5B/1.5B/3B establish ground-truth benchmark scores for calibration error computation; LoRA r=16 alpha=32 1-epoch training on pure instruction data should preserve base model capability\", \"log_path\": \"N/A (parent entry)\", \"notes\": \"Parent entry for 3 sub-experiments (05B/15B/3B). All confirmed running.\", \"retry_count\": 0, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:36:52.832Z\"}, \"exp_001_sft_0pct_3B_s123\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123\", \"completed_at\": \"2026-05-14T00:23:18.290Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T20:39:01.606Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-14T00:16:17.727184+00:00\"}]}, \"hypothesis\": \"0% dosage clean baseline Qwen2.5-3B seed=123 (second seed for variance estimation)\", \"metrics\": {\"adapter_model_mb\": 114, \"adapter_size_mb\": 488, \"checkpoint_size_mb\": 488, \"epochs\": 1, \"final_loss\": 1.114, \"mean_token_accuracy\": 0.7505, \"mean_train_loss\": 1.1309, \"steps_completed\": 3125, \"total_steps\": 3125, \"total_tokens\": 19555717, \"train_samples_per_second\": 3.91, \"training_time_min\": 213.1}, \"notes\": \"OOM 修复后重提交 --gpu 3 (物理 GPU 3)。Worker 确认 PID 216249 训练中，ETA ~3.4h\", \"reproduce\": {\"finished_at\": \"2026-05-14T00:16:04.357Z\"}, \"retry_count\": 0, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s123 --seed 123 --gpu 3 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": \"50000\", \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\", \"gpu\": [\"cuda:3\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B_s123.log\", \"model_name\": \"Qwen2.5-3B\", \"pid\": \"216935\", \"seed\": 123, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-14T00:23:18.290Z\"}, \"exp_001_sft_0pct_3B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42\", \"completed_at\": \"2026-05-13T23:25:49.016Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:44:40.471Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-13T23:23:43.393661+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B.log\", \"metrics\": {\"adapter_size_mb\": 115, \"checkpoint_size_mb\": 488, \"exit_code\": 0, \"final_loss\": 1.0736, \"mean_train_loss\": 1.1306, \"steps\": \"3125/3125\", \"token_accuracy\": 0.734, \"training_time_min\": 214.7}, \"reproduce\": {\"finished_at\": \"2026-05-13T23:23:41.844Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-3B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-3B_d000_s42 --seed 42 --gpu 5 --batch-size 1 --grad-accum 16 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:5\"], \"gpu_hours\": 3.69, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_3B.log\", \"pid\": \"210666\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T19:44:40.431Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 13268.6}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T23:25:49.016Z\"}, \"exp_001_sft_injection\": {\"completed_at\": \"2026-05-13T23:14:30.258Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T17:28:01.546Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_failed\", \"ts\": \"2026-05-13T19:18:08.635006+00:00\"}, {\"action\": \"manual_fix\", \"event\": \"status_rollback\", \"reason\": \"Cron misidentified old PID as dead → auto-failed. 3 paraphrase processes (GPU 0-2) still running. Rolled back DONE/failed → RUNNING per Director instruction.\", \"ts\": \"2026-05-13T19:32:00.000Z\"}, {\"action\": \"agent\", \"event\": \"on_failed\", \"ts\": \"2026-05-13T23:14:43.962197+00:00\"}]}, \"failure_reason\": \"\", \"hypothesis\": \"Controlled SFT contamination injection produces dose-dependent score inflation on contaminated benchmarks; 4PL+γ IRT can recover true (uncontaminated) performance from calibrated scores with proper uncertainty bounds\", \"metrics\": {\"arc_qc_pass\": 697, \"arc_qc_rate\": 0.595, \"arc_total\": 1172, \"gsm8k_qc_pass\": 228, \"gsm8k_qc_rate\": 0.173, \"gsm8k_total\": 1319, \"humaneval_total\": 164, \"mmlu_qc_pass\": 6596, \"mmlu_qc_rate\": 0.47, \"mmlu_total\": 14042}, \"notes\": \"MMLU paraphrase 3-attempt QC 重试流程: Attempt 1 ✅ (878 batches, 4112/14042 QC pass 29.3%, ~90min). Attempt 2 进行中 (v2重启, 439 batches total, 进度~22%). Attempt 3 待定. 输出在全部 attempt 结束后一次性写出 mmlu_paraphrases.json. GSM8K ✅ 1319条(QC 17.3%), ARC ✅ 1172条(QC 59.5%).\", \"reproduce\": {\"finished_at\": \"2026-05-13T23:14:29.355Z\"}, \"retry_count\": 0, \"spec\": {\"command\": \"Phase 1 paraphrase: GPU 0 MMLU (PID 204467 v3, vLLM bs=16). GSM8K + ARC completed.\", \"data_count\": \"45 SFT runs + 90 eval runs (original+paraphrased)\", \"data_path\": \"MMLU+GSM8K+ARC-Challenge+HumanEval paraphrases → SFT data mixing\", \"gpu\": \"cuda:0 (MMLU vLLM, still running). cuda:1/2 freed (GSM8K+ARC done).\", \"model_name\": \"Qwen2.5-0.5B/1.5B/3B (LoRA SFT), Qwen2.5-7B-Instruct (paraphrase)\", \"note\": \"GSM8K: 1319 paraphrases (228 QC pass, 17.3%). ARC: 1172 paraphrases (697 QC pass, 59.5%). MMLU: Attempt 1 done (878 batches, 29.3% QC), Attempt 2 in progress (439 batches total, ~22%), Attempt 3 pending. HumanEval: done (appendix per D009).\", \"pid\": \"204467\", \"seed\": \"42,123,456\", \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T23:21:54.827Z\"}, \"exp_001_sft_0pct_15B_s123\": {\"completed_at\": \"2026-05-13T22:30:26.882Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T20:35:07.346Z\", \"hypothesis\": \"0% dosage clean baseline Qwen2.5-1.5B seed=123 (second seed for variance estimation)\", \"metrics\": {\"token_acc\": 0.731, \"train_loss\": 1.2602, \"train_time_min\": 101.5}, \"notes\": \"OOM 修复后重提交 --gpu 2 (物理 GPU 2)。Worker 确认 PID 216106 训练中 (1/3125 steps, ~2.58s/it)\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s123 --seed 123 --gpu 2 --batch-size 2 --grad-accum 8 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": \"50000\", \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\", \"gpu\": [\"cuda:2\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B_s123.log\", \"model_name\": \"Qwen2.5-1.5B\", \"pid\": \"216111\", \"seed\": 123, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T22:30:26.882Z\"}, \"exp_001_sft_0pct_05B_s123\": {\"completed_at\": \"2026-05-13T22:30:25.819Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T20:35:04.879Z\", \"hypothesis\": \"0% dosage clean baseline Qwen2.5-0.5B seed=123 (second seed for variance estimation)\", \"metrics\": {\"token_acc\": 0.676, \"train_loss\": 1.5393, \"train_time_min\": 54.5}, \"notes\": \"OOM 修复后重提交 --gpu 1 (物理 GPU 1)。Worker 确认 PID 216028 训练中 (2/3125 steps, ~1.87s/it)\", \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s123 --seed 123 --gpu 1 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"data_count\": \"50000\", \"data_path\": \"/root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl\", \"gpu\": [\"cuda:1\"], \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B_s123.log\", \"model_name\": \"Qwen2.5-0.5B\", \"pid\": \"216033\", \"seed\": 123, \"server\": \"cqa1-21977\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T22:30:25.819Z\"}, \"exp_001_sft_0pct_15B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42\", \"completed_at\": \"2026-05-13T21:27:59.348Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:39:48.369Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-13T21:25:42.551081+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B.log\", \"metrics\": {\"adapter_size_mb\": 71, \"checkpoint_size_mb\": 313, \"exit_code\": 0, \"final_loss\": 1.2039, \"mean_train_loss\": 1.2599, \"steps\": \"3125/3125\", \"token_accuracy\": 0.711, \"training_time_min\": 101.5}, \"reproduce\": {\"finished_at\": \"2026-05-13T21:25:40.979Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-1.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-1.5B_d000_s42 --seed 42 --gpu 4 --batch-size 2 --grad-accum 8 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:4\"], \"gpu_hours\": 1.78, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_15B.log\", \"pid\": \"210116\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T19:41:11.760Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 6407.6}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T21:27:59.348Z\"}, \"exp_001_sft_0pct_05B\": {\"checkpoint_path\": \"/root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42\", \"completed_at\": \"2026-05-13T20:36:06.744Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T19:35:01.170Z\", \"extra\": {\"hook_events\": [{\"action\": \"agent\", \"event\": \"on_complete\", \"ts\": \"2026-05-13T20:33:54.496690+00:00\"}]}, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B.log\", \"metrics\": {\"adapter_size_mb\": 34, \"checkpoint_size_mb\": 166, \"exit_code\": 0, \"final_loss\": 1.4894, \"mean_train_loss\": 1.5388, \"steps\": \"3125/3125\", \"token_accuracy\": 0.682, \"training_time_min\": 52.9}, \"reproduce\": {\"finished_at\": \"2026-05-13T20:33:53.420Z\"}, \"retry_count\": 0, \"spec\": {\"account\": \"root\", \"backend\": \"tmux\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export TOKENIZERS_PARALLELISM=false && python /root/contamcal-irt-calibration/exp001/train_sft.py --model-name /root/autodl-tmp/.hf_cache/Qwen/Qwen2.5-0.5B --data-path /root/autodl-tmp/exp001/sft_data/sft_dosage_000.jsonl --output-dir /root/autodl-tmp/exp001/checkpoints/Qwen2.5-0.5B_d000_s42 --seed 42 --gpu 3 --batch-size 4 --grad-accum 4 --cache-dir /root/autodl-tmp/.hf_cache\\\"\", \"gpu\": [\"cuda:3\"], \"gpu_hours\": 0.98, \"log_path\": \"~/runs/contamcal-irt-calibration/exp_001_sft_0pct_05B.log\", \"pid\": \"208933\", \"server\": \"cqa1-21977\", \"submitted_at\": \"2026-05-13T19:37:23.024Z\", \"submitted_via\": \"submit_training_job\", \"wall_clock_seconds\": 3523.7}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T20:37:01.562Z\"}, \"mvp_sim_confounding\": {\"completed_at\": \"2026-05-13T16:28:42.378Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T04:39:19.345Z\", \"hypothesis\": \"4PL+γ IRT model can still separate γ from θ when exposure is confounded with ability (corr≈0.4); if not, need model-level random effect for exposure\", \"metrics\": {\"actual_confound_corr\": 0.3814, \"divergent_pct\": 0, \"fit_time_sec\": 832, \"gamma_ci_covers_true\": true, \"gamma_ci_excludes_zero\": true, \"gamma_mean\": 0.5386, \"gamma_rel_bias\": 0.0771, \"max_rhat\": 1.007, \"min_ess\": 1371.9, \"overall\": \"PASS\", \"theta_corr\": 0.9733, \"theta_residual_exp_corr\": 0.0582, \"theta_rmse\": 0.2407}, \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"artifacts/mvp_simulation/p2_confounding_results.json\", \"command\": \"python run_p2_confounding.py\", \"data_count\": \"50 models x 300 items = 15000 responses\", \"data_path\": \"synthetic confounded (corr≈0.38)\", \"log_path\": \"/tmp/p2_confounding.log\", \"model_name\": \"4PL+γ IRT (Stan NUTS)\", \"note\": \"N_items=300 (matching Variant A PASS config), 4PL NUTS only, 4 chains 1000+1000, θ-exposure corr=0.381\", \"pid\": 202872, \"seed\": 123, \"server\": \"local-cpu\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T16:28:42.378Z\"}, \"mvp_sim_4pl_gamma\": {\"completed_at\": \"2026-05-13T10:59:01.402Z\", \"conclusion\": \"success\", \"created_at\": \"2026-05-13T04:27:47.251Z\", \"hypothesis\": \"4PL+γ IRT model can separate contamination effect (γ) from true ability (θ) on synthetic data; γ posterior recovers true value within ±0.15, θ correlation >0.9\", \"metrics\": {\"variant_a_nitems300\": {\"divergent_pct\": 0, \"fit_time_sec\": 1407.5, \"gamma_ci_covers_true\": true, \"gamma_ci_excludes_zero\": true, \"gamma_mean\": 0.466, \"gamma_rel_bias\": 0.068, \"max_rhat\": 1.003, \"overall\": \"PASS\", \"theta_corr\": 0.943, \"theta_rmse\": 0.238}}, \"retry_count\": 0, \"spec\": {\"checkpoint_path\": \"artifacts/mvp_simulation/p1_variant_results.json\", \"command\": \"python run_p1_base.py\", \"data_count\": \"50 models x 100 items = 5000 responses\", \"data_path\": \"synthetic (generated in-script)\", \"log_path\": \"/tmp/p1_variants.log\", \"model_name\": \"2PL+γ / 4PL+γ IRT (Stan)\", \"note\": \"Order: 2PL ADVI → 2PL NUTS → 4PL ADVI → 4PL NUTS\", \"pid\": 197929, \"seed\": 42, \"server\": \"local-cpu\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-13T10:59:01.402Z\"}}, \"count\": 21, \"total\": 21, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.1536}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-14T08:33:51.506Z_

<details><summary>↩ Tool result · `toolu_01She69xmaa5y5FPYVvrfGGU`</summary>

```text
1	# EXP-004 Incremental Analysis: 4PL+γ Simulation Sweep (v2)
2	
3	**Date**: 2026-05-14T08:30 | **Status**: 43/120 runs complete (35.8%) | **Previous**: 27/120
4	
5	## Progress
6	
7	| Condition | Seeds | Status | Δ vs last |
8	|-----------|-------|--------|-----------|
9	| auc0.55_n20_prior1.0_binary | 10/10 | ✓ Complete | — |
10	| auc0.55_n50_prior1.0_binary | 10/10 | ✓ Complete | — |
11	| auc0.55_n100_prior1.0_binary | 7/10 | Running | +1 seed |
12	| auc0.80_n20_prior1.0_binary | 10/10 | ✓ Complete | **NEW** |
13	| auc0.80_n50_prior1.0_binary | 6/10 | Running | +5 seeds |
14	| auc0.65_n{20,50,100} | 0/30 | Not started | — |
15	| auc0.90_n{20,50,100} | 0/30 | Not started | — |
16	| auc0.80_n100 | 0/10 | Not started | — |
17	
18	Currently running: auc0.80_n50, seed 6/10. ETA for full sweep: ~20–30h.
19	
20	## Table 1: γ Recovery Metrics
21	
22	| AUC | N | Seeds | γ Bias | γ RMSE | CI95 Width | Cov95 | Cov80 | Cov50 | Power | θ Corr |
23	|-----|---|-------|--------|--------|------------|-------|-------|-------|-------|--------|
24	| 0.55 | 20 | 10 | +0.020 | 0.040 | 0.133 | 0.80 | 0.80 | 0.50 | 1.00 | 0.958 |
25	| 0.55 | 50 | 10 | +0.015 | 0.026 | 0.087 | 0.90 | 0.70 | 0.50 | 1.00 | 0.947 |
26	| 0.55 | 100 | 7 | −0.003 | 0.005 | 0.064 | 1.00 | 1.00 | 1.00 | 1.00 | 0.951 |
27	| **0.80** | **20** | **10** | **−0.016** | **0.081** | **0.258** | **0.90** | **0.70** | **0.40** | **1.00** | **0.972** |
28	| **0.80** | **50** | **6** | **+0.005** | **0.035** | **0.162** | **1.00** | **0.83** | **0.50** | **1.00** | **0.968** |
29	
30	Bold = new or substantially updated since last analysis.
31	
32	## Finding 1: AUC=0.80 CI Width Anomaly — CONFIRMED
33	
34	Previously flagged with 1 seed. Now confirmed with 16 seeds across two N values:
35	
36	| N_models | CI95 Width (AUC=0.55) | CI95 Width (AUC=0.80) | Ratio |
37	|----------|----------------------|----------------------|-------|
38	| 20 | 0.133 | 0.258 | **1.95×** |
39	| 50 | 0.087 | 0.162 | **1.86×** |
40	
41	**Mechanism: posterior variance inflation, not bias.** Posterior γ SD at AUC=0.80 is ~2× AUC=0.55:
42	
43	| N | Post. SD (AUC=0.55) | Post. SD (AUC=0.80) | Ratio |
44	|---|---------------------|---------------------|-------|
45	| 20 | 0.034 | 0.066 | 1.94× |
46	| 50 | 0.022 | 0.041 | 1.86× |
47	
48	**Interpretation**: higher-AUC exposure is more collinear with latent ability (θ). The model struggles to disentangle "answered correctly because exposed to benchmark" vs "answered correctly because more capable." This is a fundamental identifiability tension — better exposure measurement paradoxically increases γ posterior uncertainty.
49	
50	## Finding 2: N_models Scaling Follows 1/√N
51	
52	| AUC | N=20→50 width ratio (actual / theory) | N=20→100 (actual / theory) |
53	|-----|---------------------------------------|----------------------------|
54	| 0.55 | 0.66 / 0.63 | 0.49 / 0.45 |
55	| 0.80 | 0.62 / 0.63 | — |
56	
57	Deviation from 1/√N is < 5% at both AUC levels.
58	
59	## Finding 3: Coverage Patterns
60	
61	**AUC=0.55 shows under-coverage at small N:**
62	- N=20: 80% (expected 95%) — driven by positive bias outliers
63	- N=50: 90%
64	- N=100: 100%
65	
66	**AUC=0.80 coverage is paradoxically better:**
67	- N=20: 90% (vs 80% at AUC=0.55)
68	- N=50: 100%
69	
70	Wider CIs at AUC=0.80 absorb variance. One extreme failure: seed 6 at N=20, bias=−0.172 (γ̂=0.328).
71	
72	**Coverage failure detail (CI95):**
73	
74	| Condition | Seed | γ̂ | Bias | CI95 |
75	|-----------|------|-----|------|------|
76	| AUC=0.55 N=20 | 7 | 0.584 | +0.084 | [0.508, 0.662] |
77	| AUC=0.55 N=20 | 9 | 0.570 | +0.070 | [0.501, 0.648] |
78	| AUC=0.55 N=50 | 8 | 0.546 | +0.046 | [0.502, 0.594] |
79	| AUC=0.80 N=20 | 6 | 0.328 | −0.172 | [0.208, 0.457] |
80	
81	AUC=0.55 failures are all upward-biased. AUC=0.80 failure is a severe downward outlier.
82	
83	## Finding 4: Bias Direction Reversal (NEW)
84	
85	| AUC | N=20 mean bias | N=50 mean bias | Direction |
86	|-----|---------------|---------------|-----------|
87	| 0.55 | +0.020 | +0.015 | positive (γ overestimated) |
88	| 0.80 | −0.016 | +0.005 | negative/neutral (γ underestimated at small N) |
89	
90	At AUC=0.80 N=20, mean bias is negative: ability-exposure collinearity causes the model to partially absorb the contamination signal into θ, shrinking γ̂.
91	
92	## Finding 5: 100% Power
93	
94	All 43 runs have CI95 excluding zero. Smallest lower CI bound: 0.208 (AUC=0.80, N=20, seed 6). Even the worst case decisively rejects γ=0.
95	
96	## Finding 6: MCMC Quality Flawless
97	
98	| Metric | Value |
99	|--------|-------|
100	| Total divergences | 0 / 43 runs |
101	| Worst Rhat | 1.010 |
102	| Min ESS (worst) | 439 (auc0.55_n100 seed 2) |
103	
104	## Finding 7: θ Recovery Improves at Higher AUC
105	
106	| AUC | N=20 θ_corr | N=50 θ_corr |
107	|-----|------------|------------|
108	| 0.55 | 0.958 | 0.947 |
109	| 0.80 | 0.972 | 0.968 |
110	
111	Higher AUC → better θ recovery. More informative exposure signal provides additional information about ability.
112	
113	## Computation Time
114	
115	| Condition | Avg time/seed |
116	|-----------|--------------|
117	| AUC=0.55, N=20 | 321s |
118	| AUC=0.55, N=50 | 1,295s |
119	| AUC=0.55, N=100 | 3,793s |
120	| AUC=0.80, N=20 | 425s |
121	| AUC=0.80, N=50 | 770s |
122	
123	AUC=0.80 runs faster than AUC=0.55 at matched N — more informative exposure → faster MCMC convergence.
124	
125	---
126	
127	## Paper-Ready Claims
128	
129	### ✅ Claim 1: γ identifiable at near-chance exposure quality
130	At AUC=0.55, RMSE ≤ 0.04 (N=20), ≤ 0.005 (N=100). 100% power. 30 seeds.
131	
132	### ✅ Claim 2: Precision scales as O(1/√N_models)
133	CI width ratios match theoretical 1/√N within 5%. Verified at AUC=0.55 (3 N levels) and AUC=0.80 (2 N levels).
134	
135	### ✅ Claim 3: Exposure-ability collinearity inflates γ posterior at high AUC
136	CI width at AUC=0.80 is 1.85–1.95× AUC=0.55. Posterior SD ratio matches. 16 seeds across 2×2 conditions. **Novel and counterintuitive finding.**
137	
138	### ✅ Claim 4: Robust detection power
139	43/43 runs detect γ ≠ 0. Smallest CI lower bound = 0.208.
140	
141	### ⚠️ Claim 5: Bias direction reversal across AUC
142	Positive bias at AUC=0.55, negative at AUC=0.80. Plausible mechanism. Needs AUC=0.65/0.90 to confirm monotonic trend.
143	
144	---
145	
146	## Still Needed
147	
148	1. **AUC=0.65 and AUC=0.90** (0/60 seeds): maps the full AUC→precision curve
149	2. **AUC=0.80 N=100** (0/10): tests whether collinearity effect persists at large N
150	3. **Remaining seeds**: 3 for auc0.55_n100, 4 for auc0.80_n50
151	4. **Prior sensitivity**: only prior_sd=1.0 tested so far
152	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "408794f4-d2f4-496b-8fd7-710b69508610",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/exp004_incremental_analysis.md",
      "content": "# EXP-004 Incremental Analysis: 4PL+γ Simulation Sweep (v2)\n\n**Date**: 2026-05-14T08:30 | **Status**: 43/120 runs complete (35.8%) | **Previous**: 27/120\n\n## Progress\n\n| Condition | Seeds | Status | Δ vs last |\n|-----------|-------|--------|-----------|\n| auc0.55_n20_prior1.0_binary | 10/10 | ✓ Complete | — |\n| auc0.55_n50_prior1.0_binary | 10/10 | ✓ Complete | — |\n| auc0.55_n100_prior1.0_binary | 7/10 | Running | +1 seed |\n| auc0.80_n20_prior1.0_binary | 10/10 | ✓ Complete | **NEW** |\n| auc0.80_n50_prior1.0_binary | 6/10 | Running | +5 seeds |\n| auc0.65_n{20,50,100} | 0/30 | Not started | — |\n| auc0.90_n{20,50,100} | 0/30 | Not started | — |\n| auc0.80_n100 | 0/10 | Not started | — |\n\nCurrently running: auc0.80_n50, seed 6/10. ETA for full sweep: ~20–30h.\n\n## Table 1: γ Recovery Metrics\n\n| AUC | N | Seeds | γ Bias | γ RMSE | CI95 Width | Cov95 | Cov80 | Cov50 | Power | θ Corr |\n|-----|---|-------|--------|--------|------------|-------|-------|-------|-------|--------|\n| 0.55 | 20 | 10 | +0.020 | 0.040 | 0.133 | 0.80 | 0.80 | 0.50 | 1.00 | 0.958 |\n| 0.55 | 50 | 10 | +0.015 | 0.026 | 0.087 | 0.90 | 0.70 | 0.50 | 1.00 | 0.947 |\n| 0.55 | 100 | 7 | −0.003 | 0.005 | 0.064 | 1.00 | 1.00 | 1.00 | 1.00 | 0.951 |\n| **0.80** | **20** | **10** | **−0.016** | **0.081** | **0.258** | **0.90** | **0.70** | **0.40** | **1.00** | **0.972** |\n| **0.80** | **50** | **6** | **+0.005** | **0.035** | **0.162** | **1.00** | **0.83** | **0.50** | **1.00** | **0.968** |\n\nBold = new or substantially updated since last analysis.\n\n## Finding 1: AUC=0.80 CI Width Anomaly — CONFIRMED\n\nPreviously flagged with 1 seed. Now confirmed with 16 seeds across two N values:\n\n| N_models | CI95 Width (AUC=0.55) | CI95 Width (AUC=0.80) | Ratio |\n|----------|----------------------|----------------------|-------|\n| 20 | 0.133 | 0.258 | **1.95×** |\n| 50 | 0.087 | 0.162 | **1.86×** |\n\n**Mechanism: posterior variance inflation, not bias.** Posterior γ SD at AUC=0.80 is ~2× AUC=0.55:\n\n| N | Post. SD (AUC=0.55) | Post. SD (AUC=0.80) | Ratio |\n|---|---------------------|---------------------|-------|\n| 20 | 0.034 | 0.066 | 1.94× |\n| 50 | 0.022 | 0.041 | 1.86× |\n\n**Interpretation**: higher-AUC exposure is more collinear with latent ability (θ). The model struggles to disentangle \"answered correctly because exposed to benchmark\" vs \"answered correctly because more capable.\" This is a fundamental identifiability tension — better exposure measurement paradoxically increases γ posterior uncertainty.\n\n## Finding 2: N_models Scaling Follows 1/√N\n\n| AUC | N=20→50 width ratio (actual / theory) | N=20→100 (actual / theory) |\n|-----|---------------------------------------|----------------------------|\n| 0.55 | 0.66 / 0.63 | 0.49 / 0.45 |\n| 0.80 | 0.62 / 0.63 | — |\n\nDeviation from 1/√N is < 5% at both AUC levels.\n\n## Finding 3: Coverage Patterns\n\n**AUC=0.55 shows under-coverage at small N:**\n- N=20: 80% (expected 95%) — driven by positive bias outliers\n- N=50: 90%\n- N=100: 100%\n\n**AUC=0.80 coverage is paradoxically better:**\n- N=20: 90% (vs 80% at AUC=0.55)\n- N=50: 100%\n\nWider CIs at AUC=0.80 absorb variance. One extreme failure: seed 6 at N=20, bias=−0.172 (γ̂=0.328).\n\n**Coverage failure detail (CI95):**\n\n| Condition | Seed | γ̂ | Bias | CI95 |\n|-----------|------|-----|------|------|\n| AUC=0.55 N=20 | 7 | 0.584 | +0.084 | [0.508, 0.662] |\n| AUC=0.55 N=20 | 9 | 0.570 | +0.070 | [0.501, 0.648] |\n| AUC=0.55 N=50 | 8 | 0.546 | +0.046 | [0.502, 0.594] |\n| AUC=0.80 N=20 | 6 | 0.328 | −0.172 | [0.208, 0.457] |\n\nAUC=0.55 failures are all upward-biased. AUC=0.80 failure is a severe downward outlier.\n\n## Finding 4: Bias Direction Reversal (NEW)\n\n| AUC | N=20 mean bias | N=50 mean bias | Direction |\n|-----|---------------|---------------|-----------|\n| 0.55 | +0.020 | +0.015 | positive (γ overestimated) |\n| 0.80 | −0.016 | +0.005 | negative/neutral (γ underestimated at small N) |\n\nAt AUC=0.80 N=20, mean bias is negative: ability-exposure collinearity causes the model to partially absorb the contamination signal into θ, shrinking γ̂.\n\n## Finding 5: 100% Power\n\nAll 43 runs have CI95 excluding zero. Smallest lower CI bound: 0.208 (AUC=0.80, N=20, seed 6). Even the worst case decisively rejects γ=0.\n\n## Finding 6: MCMC Quality Flawless\n\n| Metric | Value |\n|--------|-------|\n| Total divergences | 0 / 43 runs |\n| Worst Rhat | 1.010 |\n| Min ESS (worst) | 439 (auc0.55_n100 seed 2) |\n\n## Finding 7: θ Recovery Improves at Higher AUC\n\n| AUC | N=20 θ_corr | N=50 θ_corr |\n|-----|------------|------------|\n| 0.55 | 0.958 | 0.947 |\n| 0.80 | 0.972 | 0.968 |\n\nHigher AUC → better θ recovery. More informative exposure signal provides additional information about ability.\n\n## Computation Time\n\n| Condition | Avg time/seed |\n|-----------|--------------|\n| AUC=0.55, N=20 | 321s |\n| AUC=0.55, N=50 | 1,295s |\n| AUC=0.55, N=100 | 3,793s |\n| AUC=0.80, N=20 | 425s |\n| AUC=0.80, N=50 | 770s |\n\nAUC=0.80 runs faster than AUC=0.55 at matched N — more informative exposure → faster MCMC convergence.\n\n---\n\n## Paper-Ready Claims\n\n### ✅ Claim 1: γ identifiable at near-chance exposure quality\nAt AUC=0.55, RMSE ≤ 0.04 (N=20), ≤ 0.005 (N=100). 100% power. 30 seeds.\n\n### ✅ Claim 2: Precision scales as O(1/√N_models)\nCI width ratios match theoretical 1/√N within 5%. Verified at AUC=0.55 (3 N levels) and AUC=0.80 (2 N levels).\n\n### ✅ Claim 3: Exposure-ability collinearity inflates γ posterior at high AUC\nCI width at AUC=0.80 is 1.85–1.95× AUC=0.55. Posterior SD ratio matches. 16 seeds across 2×2 conditions. **Novel and counterintuitive finding.**\n\n### ✅ Claim 4: Robust detection power\n43/43 runs detect γ ≠ 0. Smallest CI lower bound = 0.208.\n\n### ⚠️ Claim 5: Bias direction reversal across AUC\nPositive bias at AUC=0.55, negative at AUC=0.80. Plausible mechanism. Needs AUC=0.65/0.90 to confirm monotonic trend.\n\n---\n\n## Still Needed\n\n1. **AUC=0.65 and AUC=0.90** (0/60 seeds): maps the full AUC→precision curve\n2. **AUC=0.80 N=100** (0/10): tests whether collinearity effect persists at large N\n3. **Remaining seeds**: 3 for auc0.55_n100, 4 for auc0.80_n50\n4. **Prior sensitivity**: only prior_sd=1.0 tested so far\n",
      "numLines": 152,
      "startLine": 1,
      "totalLines": 152
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
Now I have all the data I need. Let me also check for the eval results from exp_001_eval_05B_d005 which doesn't have metrics in the registry. Let me also look for any MVP simulation results files that might have more detail. Let me also check if there are any eval results for the 1.5B d100 model.

Let me organize what I have:

**Phase 3 SFT + Phase 4 Eval Results:**

Eval experiments with metrics:
1. `exp_001_eval_05B_d000_s42_v5` (legacy): MMLU=0.4049, GSM8K=0.3647, ARC=0.378, HumanEval=0.1098


2. `exp_001_eval_05B_d000_s123` (legacy): MMLU=0.4182, GSM8K=0.3404, ARC=0.3976, HumanEval=0.1037
3. `exp_001_eval_05B_d100_v5` (legacy): MMLU=0.2322, GSM8K=0.3571, ARC=0.227, HumanEval=0.0854
4. `exp_001_eval_05B_d005` (legacy): No metrics in registry
5. `exp_001_eval_3B_d000_s42` (legacy): Still checking for results...

Looking at the 3B and 15B model variants, the 3B models show strong MMLU and ARC performance around 0.63-0.82 range, while the 15B variants push higher on GSM8K (0.63-0.64) and maintain solid ARC scores above 0.76. There's also an SFT-only variant mentioned without evaluation metrics yet.

Now I'm checking which experiments use the legacy multiple-choice format versus the aligned format—several of the 5B evaluations are marked as legacy, which might affect how I interpret their results. I'm noticing the 1.5B evals in the registry only have d000 variants, not the d100 mentioned in the task description. For the 3B models, neither evaluation has an explicit format note like the 0.5B ones do. I should also flag that exp_001_eval_05B_d005 shows a success conclusion but lacks any metrics data. Now I'm organizing this into structured tables comparing the models across their dosage levels.

Generating markdown table... Now I'm looking at the rest of the performance metrics, and those 3B GSM8K scores are surprisingly low—0.117 and 0.1759 compared to 1.5B getting 0.63, which doesn't make intuitive sense, but I'll report the data as it is. I need to verify the format specification for the 1.5B and 3B models since only the 0.5B notes explicitly mention "legacy mc_format" and there's no clear documentation for the larger models.

Looking at the evaluation scripts and timeline, all the evals use the same evaluate.py script, but the 0.5B runs were submitted earlier than the 1.5B and 3B runs, so there might have been a format change between them. The 0.5B evals have a warning about legacy format, while the 1.5B and 3B evals don't have this warning, but they also don't explicitly state they're using the aligned format either. Without clearer documentation, I'll mark the format for 1.5B and 3B as unknown and flag this as something that needs clarification. Now I'm compiling the missing evaluations across the different model sizes and dosages—several combinations never ran their fine-tuning or evaluation steps, particularly the 1.5B and 3B variants with certain seed and dosage combinations. Let me pull together the output tables with what data I have from the registry.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "dbbdb4de-92db-4cf0-854e-07809fa6251c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xz2RnZNqLGrWLx5vi8Jm83",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20419,
      "cache_read_input_tokens": 24203,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 20419
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

Now I have all the data. Let me check if the target directory exists and write the results tables.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "de19dd39-7f54-4a01-ae26-468a4cdad36c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xz2RnZNqLGrWLx5vi8Jm83",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20419,
      "cache_read_input_tokens": 24203,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 20419
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

<details open><summary>🔧 Tool call — Bash · `toolu_01FmJBPJjoULKDGWMizkApYo`</summary>

```json
{
  "command": "mkdir -p /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft",
  "description": "Create paper_draft directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "72821160-9853-418b-be20-7fe0c4d062e0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xz2RnZNqLGrWLx5vi8Jm83",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20419,
      "cache_read_input_tokens": 24203,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 20419
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

_source line 15 · 2026-05-14T08:34:41.740Z_

<details><summary>↩ Tool result · `toolu_01FmJBPJjoULKDGWMizkApYo`</summary>

```text
(Bash completed with no output)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "8c29f1ee-89dd-4ae1-b212-c7607cd671ad",
  "tool_use_result": {
    "stdout": "",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": true
  }
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Write · `toolu_0123EWkmFo41MKcG2sxFx1wY`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/results_tables.md",
  "content": "# ContamCal Results Tables (for EMNLP 2026 paper)\n\n**Generated**: 2026-05-14 | **Source**: experiment registry + exp004 analysis artifact\n\n---\n\n## Table 1: Phase 3-4 SFT Eval — Benchmark Scores (Model × Dosage)\n\nAll models: Qwen2.5 family, LoRA r=16 α=32, 1 epoch SFT.\n\n| Model | Dosage | Seed | MMLU | GSM8K | ARC-C | HumanEval | mc_format | exp_id |\n|-------|--------|------|------|-------|-------|-----------|-----------|--------|\n| 0.5B | 0% | 42 | 0.4049 | 0.3647 | 0.3780 | 0.1098 | **legacy** | exp_001_eval_05B_d000_s42_v5 |\n| 0.5B | 0% | 123 | 0.4182 | 0.3404 | 0.3976 | 0.1037 | **legacy** | exp_001_eval_05B_d000_s123 |\n| 0.5B | 5% | 42 | — | — | — | — | legacy | exp_001_eval_05B_d005 ^1 |\n| 0.5B | 100% | 42 | 0.2322 | 0.3571 | 0.2270 | 0.0854 | **legacy** | exp_001_eval_05B_d100_v5 |\n| 1.5B | 0% | 42 | 0.5753 | 0.6368 | 0.7756 | 0.1280 | TBD ^2 | exp_001_eval_15B_d000_s42_v2 |\n| 1.5B | 0% | 123 | 0.5762 | 0.6331 | 0.7662 | 0.1707 | TBD ^2 | exp_001_eval_15B_d000_s123 |\n| 1.5B | 5% | — | — | — | — | — | — | **missing** |\n| 1.5B | 100% | — | — | — | — | — | — | **missing** ^3 |\n| 3B | 0% | 42 | 0.6340 | 0.1170 | 0.8220 | 0.1160 | TBD ^2 | exp_001_eval_3B_d000_s42 |\n| 3B | 0% | 123 | 0.6362 | 0.1759 | 0.8294 | 0.0854 | TBD ^2 | exp_001_eval_3B_d000_s123 |\n| 3B | 5% | — | — | — | — | — | — | **missing** |\n| 3B | 100% | — | — | — | — | — | — | **missing** |\n\n### Notes\n- ^1: exp_001_eval_05B_d005 registered as success but **no metrics in registry**. Need to extract from result files on server.\n- ^2: 1.5B/3B eval format (legacy vs aligned) not annotated in registry. Needs verification against D017 decision.\n- ^3: 1.5B d100 SFT is complete (exp_001_sft_d100_15B_v2), but eval has not been run.\n\n### D017 Format Compatibility\n- **legacy mc_format**: 0.5B evals confirmed legacy. MC scores may undercount due to format mismatch (e.g., 0.5B d100 MMLU=0.232 is -17.3pp below d000 baseline — likely format artifact, not real degradation).\n- **aligned mc_format**: Not yet confirmed for any completed eval.\n- **Implication**: 0.5B dose-response (d000 vs d100) is NOT valid for paper analysis until re-run with aligned format.\n\n---\n\n## Table 2: Baseline Cross-Seed Consistency (d000 only)\n\n| Model | Metric | Seed 42 | Seed 123 | Δ | CV% |\n|-------|--------|---------|----------|---|-----|\n| 0.5B | MMLU | 0.4049 | 0.4182 | 0.013 | 2.2% |\n| 0.5B | GSM8K | 0.3647 | 0.3404 | 0.024 | 4.9% |\n| 0.5B | ARC-C | 0.3780 | 0.3976 | 0.020 | 3.6% |\n| 0.5B | HumanEval | 0.1098 | 0.1037 | 0.006 | 4.0% |\n| 1.5B | MMLU | 0.5753 | 0.5762 | 0.001 | 0.1% |\n| 1.5B | GSM8K | 0.6368 | 0.6331 | 0.004 | 0.4% |\n| 1.5B | ARC-C | 0.7756 | 0.7662 | 0.009 | 0.9% |\n| 1.5B | HumanEval | 0.1280 | 0.1707 | 0.043 | 20.2% |\n| 3B | MMLU | 0.6340 | 0.6362 | 0.002 | 0.2% |\n| 3B | GSM8K | 0.1170 | 0.1759 | 0.059 | 28.4% |\n| 3B | ARC-C | 0.8220 | 0.8294 | 0.007 | 0.6% |\n| 3B | HumanEval | 0.1160 | 0.0854 | 0.031 | 21.5% |\n\n**Observation**: MC benchmarks (MMLU, ARC) are stable across seeds (CV <5%). Generation benchmarks (HumanEval, GSM8K on 3B) show high variance (CV 20-28%), expected for small sample sizes (164 HumanEval, 1319 GSM8K).\n\n**Anomaly**: 3B GSM8K scores (0.117, 0.176) are lower than 1.5B (0.637, 0.633). This is unexpected for a larger model and may indicate an eval issue — needs investigation.\n\n---\n\n## Table 3: MVP Simulation — 4PL+γ Base Recovery (exp: mvp_sim_4pl_gamma)\n\nConfig: 50 models × 300 items, Stan NUTS 4 chains × 1000+1000, seed=42.\n\n| Variant | γ_mean | γ_rel_bias | CI95 covers true | CI95 excludes 0 | θ_corr | θ_RMSE | Divergent% | Max Rhat | Min ESS | Fit time (s) |\n|---------|--------|------------|-----------------|-----------------|--------|--------|------------|----------|---------|--------------|\n| 4PL+γ NUTS (N_items=300) | 0.466 | 0.068 | Yes | Yes | 0.943 | 0.238 | 0% | 1.003 | — | 1407.5 |\n\n**Verdict**: PASS. γ identified with <7% relative bias, θ correlation >0.94.\n\n---\n\n## Table 4: MVP Simulation — Confounding Robustness (exp: mvp_sim_confounding)\n\nConfig: 50 models × 300 items, θ-exposure corr=0.381, Stan NUTS 4 chains × 1000+1000, seed=123.\n\n| Metric | Value | Pass criterion | Status |\n|--------|-------|----------------|--------|\n| γ_mean | 0.5386 | — | — |\n| γ_rel_bias | 0.077 | <0.15 | PASS |\n| γ CI95 covers true | Yes | — | PASS |\n| γ CI95 excludes 0 | Yes | — | PASS |\n| θ_corr | 0.9733 | >0.9 | PASS |\n| θ_RMSE | 0.2407 | — | — |\n| θ_residual × exposure corr | 0.0582 | <0.1 (separation) | PASS |\n| Divergent% | 0% | <1% | PASS |\n| Max Rhat | 1.007 | <1.05 | PASS |\n| Min ESS | 1371.9 | >400 | PASS |\n| Fit time (s) | 832 | — | — |\n\n**Verdict**: PASS. γ separable from θ even under moderate ability-exposure confounding.\n\n---\n\n## Table 5: EXP-004 Simulation Sweep — γ Recovery by AUC × N_models\n\nConfig: 4PL+γ Stan NUTS, prior_sd=1.0, binary exposure. 43/120 runs complete (35.8%).\n\n| AUC | N_models | Seeds done | γ Bias | γ RMSE | CI95 Width | Cov95 | Power | θ_corr |\n|-----|----------|------------|--------|--------|------------|-------|-------|--------|\n| 0.55 | 20 | 10/10 | +0.020 | 0.040 | 0.133 | 0.80 | 1.00 | 0.958 |\n| 0.55 | 50 | 10/10 | +0.015 | 0.026 | 0.087 | 0.90 | 1.00 | 0.947 |\n| 0.55 | 100 | 7/10 | −0.003 | 0.005 | 0.064 | 1.00 | 1.00 | 0.951 |\n| 0.80 | 20 | 10/10 | −0.016 | 0.081 | 0.258 | 0.90 | 1.00 | 0.972 |\n| 0.80 | 50 | 6/10 | +0.005 | 0.035 | 0.162 | 1.00 | 1.00 | 0.968 |\n| 0.65 | 20/50/100 | 0/30 | — | — | — | — | — | — |\n| 0.80 | 100 | 0/10 | — | — | — | — | — | — |\n| 0.90 | 20/50/100 | 0/30 | — | — | — | — | — | — |\n\n**Source**: artifacts/exp004_incremental_analysis.md\n\n### Key Findings (paper-ready)\n1. **γ identifiable at near-chance exposure quality**: AUC=0.55, RMSE ≤ 0.04 (N=20), ≤ 0.005 (N=100). 100% power across all 43 runs.\n2. **Precision scales as O(1/√N)**: CI width ratios match theory within 5%.\n3. **High-AUC exposure inflates γ posterior**: CI95 width at AUC=0.80 is 1.85–1.95× AUC=0.55 (ability-exposure collinearity).\n4. **Bias direction reversal**: positive bias at AUC=0.55, negative at AUC=0.80 (needs AUC=0.65/0.90 to confirm trend).\n\n---\n\n## Table 6: SFT Training Summary (Phase 3)\n\n| Model | Dosage | Seed | Final Loss | Token Acc | Train Time (min) | exp_id |\n|-------|--------|------|------------|-----------|-------------------|--------|\n| 0.5B | 0% | 42 | 1.489 | 0.682 | 52.9 | exp_001_sft_0pct_05B |\n| 0.5B | 0% | 123 | — | 0.676 | 54.5 | exp_001_sft_0pct_05B_s123 |\n| 0.5B | 5% | 42 | 1.478 | 0.667 | 56.1 | exp_001_sft_d005_05B_v3 |\n| 0.5B | 100% | 42 | 1.594 | 0.666 | 68.9 | exp_001_sft_d100_05B |\n| 1.5B | 0% | 42 | 1.204 | 0.711 | 101.5 | exp_001_sft_0pct_15B |\n| 1.5B | 0% | 123 | — | 0.731 | 101.5 | exp_001_sft_0pct_15B_s123 |\n| 1.5B | 100% | 42 | — | — | — | exp_001_sft_d100_15B_v2 ^4 |\n| 3B | 0% | 42 | 1.074 | 0.734 | 214.7 | exp_001_sft_0pct_3B |\n| 3B | 0% | 123 | 1.114 | 0.751 | 213.1 | exp_001_sft_0pct_3B_s123 |\n\n^4: SFT complete but training metrics not recorded in registry (only status=DONE).\n\n---\n\n## Gap Analysis: What's Missing for Paper\n\n### Critical (blocks paper tables)\n1. **Aligned-format evals for ALL models/dosages**: legacy format results (all 0.5B evals) are not usable for dose-response analysis. Need evaluate.py with aligned mc_format.\n2. **1.5B d100 eval**: SFT done, eval not yet run.\n3. **Contaminated dosage evals for 1.5B and 3B**: No d005 or d100 evals exist for 1.5B (only d000) or 3B (only d000).\n4. **0.5B d005 eval metrics**: Run completed but metrics not captured in registry.\n\n### Important (strengthens paper)\n5. **3B d005 and d100 SFT + eval**: Needed for full 3-model × 3-dosage matrix.\n6. **1.5B d005 SFT + eval**: Needed for mid-dosage data point.\n7. **EXP-004 remaining 77 runs** (AUC=0.65/0.90, remaining seeds): Maps full AUC→precision curve.\n\n### Nice-to-have\n8. **Seed 123 for contaminated conditions** (d005, d100): Variance estimation on contaminated models.\n9. **EXP-004 prior sensitivity** (prior_sd ≠ 1.0): Only one prior tested so far.\n\n### Current Coverage Matrix\n\n| | d000 s42 | d000 s123 | d005 s42 | d100 s42 |\n|---|----------|-----------|----------|----------|\n| 0.5B | legacy | legacy | no metrics ^1 | legacy |\n| 1.5B | TBD ^2 | TBD ^2 | **missing** | **missing** ^3 |\n| 3B | TBD ^2 | TBD ^2 | **missing** | **missing** |\n\nFilled: 6/12 cells have metrics. Of those, 4 are confirmed legacy format (diagnosis only).\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "b5e7ef83-2eb6-4d81-8f33-7703f615c240",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CLJg4c6ehXSeSQaJ7xA68i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2796,
      "cache_read_input_tokens": 44622,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2796
      },
      "output_tokens": 69,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    },
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 17 · 2026-05-14T08:35:47.729Z_

<details><summary>↩ Tool result · `toolu_0123EWkmFo41MKcG2sxFx1wY`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/results_tables.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "982dd7a1-7f79-43ab-8b9a-cfecc10cd3d6",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/results_tables.md",
    "content": "# ContamCal Results Tables (for EMNLP 2026 paper)\n\n**Generated**: 2026-05-14 | **Source**: experiment registry + exp004 analysis artifact\n\n---\n\n## Table 1: Phase 3-4 SFT Eval — Benchmark Scores (Model × Dosage)\n\nAll models: Qwen2.5 family, LoRA r=16 α=32, 1 epoch SFT.\n\n| Model | Dosage | Seed | MMLU | GSM8K | ARC-C | HumanEval | mc_format | exp_id |\n|-------|--------|------|------|-------|-------|-----------|-----------|--------|\n| 0.5B | 0% | 42 | 0.4049 | 0.3647 | 0.3780 | 0.1098 | **legacy** | exp_001_eval_05B_d000_s42_v5 |\n| 0.5B | 0% | 123 | 0.4182 | 0.3404 | 0.3976 | 0.1037 | **legacy** | exp_001_eval_05B_d000_s123 |\n| 0.5B | 5% | 42 | — | — | — | — | legacy | exp_001_eval_05B_d005 ^1 |\n| 0.5B | 100% | 42 | 0.2322 | 0.3571 | 0.2270 | 0.0854 | **legacy** | exp_001_eval_05B_d100_v5 |\n| 1.5B | 0% | 42 | 0.5753 | 0.6368 | 0.7756 | 0.1280 | TBD ^2 | exp_001_eval_15B_d000_s42_v2 |\n| 1.5B | 0% | 123 | 0.5762 | 0.6331 | 0.7662 | 0.1707 | TBD ^2 | exp_001_eval_15B_d000_s123 |\n| 1.5B | 5% | — | — | — | — | — | — | **missing** |\n| 1.5B | 100% | — | — | — | — | — | — | **missing** ^3 |\n| 3B | 0% | 42 | 0.6340 | 0.1170 | 0.8220 | 0.1160 | TBD ^2 | exp_001_eval_3B_d000_s42 |\n| 3B | 0% | 123 | 0.6362 | 0.1759 | 0.8294 | 0.0854 | TBD ^2 | exp_001_eval_3B_d000_s123 |\n| 3B | 5% | — | — | — | — | — | — | **missing** |\n| 3B | 100% | — | — | — | — | — | — | **missing** |\n\n### Notes\n- ^1: exp_001_eval_05B_d005 registered as success but **no metrics in registry**. Need to extract from result files on server.\n- ^2: 1.5B/3B eval format (legacy vs aligned) not annotated in registry. Needs verification against D017 decision.\n- ^3: 1.5B d100 SFT is complete (exp_001_sft_d100_15B_v2), but eval has not been run.\n\n### D017 Format Compatibility\n- **legacy mc_format**: 0.5B evals confirmed legacy. MC scores may undercount due to format mismatch (e.g., 0.5B d100 MMLU=0.232 is -17.3pp below d000 baseline — likely format artifact, not real degradation).\n- **aligned mc_format**: Not yet confirmed for any completed eval.\n- **Implication**: 0.5B dose-response (d000 vs d100) is NOT valid for paper analysis until re-run with aligned format.\n\n---\n\n## Table 2: Baseline Cross-Seed Consistency (d000 only)\n\n| Model | Metric | Seed 42 | Seed 123 | Δ | CV% |\n|-------|--------|---------|----------|---|-----|\n| 0.5B | MMLU | 0.4049 | 0.4182 | 0.013 | 2.2% |\n| 0.5B | GSM8K | 0.3647 | 0.3404 | 0.024 | 4.9% |\n| 0.5B | ARC-C | 0.3780 | 0.3976 | 0.020 | 3.6% |\n| 0.5B | HumanEval | 0.1098 | 0.1037 | 0.006 | 4.0% |\n| 1.5B | MMLU | 0.5753 | 0.5762 | 0.001 | 0.1% |\n| 1.5B | GSM8K | 0.6368 | 0.6331 | 0.004 | 0.4% |\n| 1.5B | ARC-C | 0.7756 | 0.7662 | 0.009 | 0.9% |\n| 1.5B | HumanEval | 0.1280 | 0.1707 | 0.043 | 20.2% |\n| 3B | MMLU | 0.6340 | 0.6362 | 0.002 | 0.2% |\n| 3B | GSM8K | 0.1170 | 0.1759 | 0.059 | 28.4% |\n| 3B | ARC-C | 0.8220 | 0.8294 | 0.007 | 0.6% |\n| 3B | HumanEval | 0.1160 | 0.0854 | 0.031 | 21.5% |\n\n**Observation**: MC benchmarks (MMLU, ARC) are stable across seeds (CV <5%). Generation benchmarks (HumanEval, GSM8K on 3B) show high variance (CV 20-28%), expected for small sample sizes (164 HumanEval, 1319 GSM8K).\n\n**Anomaly**: 3B GSM8K scores (0.117, 0.176) are lower than 1.5B (0.637, 0.633). This is unexpected for a larger model and may indicate an eval issue — needs investigation.\n\n---\n\n## Table 3: MVP Simulation — 4PL+γ Base Recovery (exp: mvp_sim_4pl_gamma)\n\nConfig: 50 models × 300 items, Stan NUTS 4 chains × 1000+1000, seed=42.\n\n| Variant | γ_mean | γ_rel_bias | CI95 covers true | CI95 excludes 0 | θ_corr | θ_RMSE | Divergent% | Max Rhat | Min ESS | Fit time (s) |\n|---------|--------|------------|-----------------|-----------------|--------|--------|------------|----------|---------|--------------|\n| 4PL+γ NUTS (N_items=300) | 0.466 | 0.068 | Yes | Yes | 0.943 | 0.238 | 0% | 1.003 | — | 1407.5 |\n\n**Verdict**: PASS. γ identified with <7% relative bias, θ correlation >0.94.\n\n---\n\n## Table 4: MVP Simulation — Confounding Robustness (exp: mvp_sim_confounding)\n\nConfig: 50 models × 300 items, θ-exposure corr=0.381, Stan NUTS 4 chains × 1000+1000, seed=123.\n\n| Metric | Value | Pass criterion | Status |\n|--------|-------|----------------|--------|\n| γ_mean | 0.5386 | — | — |\n| γ_rel_bias | 0.077 | <0.15 | PASS |\n| γ CI95 covers true | Yes | — | PASS |\n| γ CI95 excludes 0 | Yes | — | PASS |\n| θ_corr | 0.9733 | >0.9 | PASS |\n| θ_RMSE | 0.2407 | — | — |\n| θ_residual × exposure corr | 0.0582 | <0.1 (separation) | PASS |\n| Divergent% | 0% | <1% | PASS |\n| Max Rhat | 1.007 | <1.05 | PASS |\n| Min ESS | 1371.9 | >400 | PASS |\n| Fit time (s) | 832 | — | — |\n\n**Verdict**: PASS. γ separable from θ even under moderate ability-exposure confounding.\n\n---\n\n## Table 5: EXP-004 Simulation Sweep — γ Recovery by AUC × N_models\n\nConfig: 4PL+γ Stan NUTS, prior_sd=1.0, binary exposure. 43/120 runs complete (35.8%).\n\n| AUC | N_models | Seeds done | γ Bias | γ RMSE | CI95 Width | Cov95 | Power | θ_corr |\n|-----|----------|------------|--------|--------|------------|-------|-------|--------|\n| 0.55 | 20 | 10/10 | +0.020 | 0.040 | 0.133 | 0.80 | 1.00 | 0.958 |\n| 0.55 | 50 | 10/10 | +0.015 | 0.026 | 0.087 | 0.90 | 1.00 | 0.947 |\n| 0.55 | 100 | 7/10 | −0.003 | 0.005 | 0.064 | 1.00 | 1.00 | 0.951 |\n| 0.80 | 20 | 10/10 | −0.016 | 0.081 | 0.258 | 0.90 | 1.00 | 0.972 |\n| 0.80 | 50 | 6/10 | +0.005 | 0.035 | 0.162 | 1.00 | 1.00 | 0.968 |\n| 0.65 | 20/50/100 | 0/30 | — | — | — | — | — | — |\n| 0.80 | 100 | 0/10 | — | — | — | — | — | — |\n| 0.90 | 20/50/100 | 0/30 | — | — | — | — | — | — |\n\n**Source**: artifacts/exp004_incremental_analysis.md\n\n### Key Findings (paper-ready)\n1. **γ identifiable at near-chance exposure quality**: AUC=0.55, RMSE ≤ 0.04 (N=20), ≤ 0.005 (N=100). 100% power across all 43 runs.\n2. **Precision scales as O(1/√N)**: CI width ratios match theory within 5%.\n3. **High-AUC exposure inflates γ posterior**: CI95 width at AUC=0.80 is 1.85–1.95× AUC=0.55 (ability-exposure collinearity).\n4. **Bias direction reversal**: positive bias at AUC=0.55, negative at AUC=0.80 (needs AUC=0.65/0.90 to confirm trend).\n\n---\n\n## Table 6: SFT Training Summary (Phase 3)\n\n| Model | Dosage | Seed | Final Loss | Token Acc | Train Time (min) | exp_id |\n|-------|--------|------|------------|-----------|-------------------|--------|\n| 0.5B | 0% | 42 | 1.489 | 0.682 | 52.9 | exp_001_sft_0pct_05B |\n| 0.5B | 0% | 123 | — | 0.676 | 54.5 | exp_001_sft_0pct_05B_s123 |\n| 0.5B | 5% | 42 | 1.478 | 0.667 | 56.1 | exp_001_sft_d005_05B_v3 |\n| 0.5B | 100% | 42 | 1.594 | 0.666 | 68.9 | exp_001_sft_d100_05B |\n| 1.5B | 0% | 42 | 1.204 | 0.711 | 101.5 | exp_001_sft_0pct_15B |\n| 1.5B | 0% | 123 | — | 0.731 | 101.5 | exp_001_sft_0pct_15B_s123 |\n| 1.5B | 100% | 42 | — | — | — | exp_001_sft_d100_15B_v2 ^4 |\n| 3B | 0% | 42 | 1.074 | 0.734 | 214.7 | exp_001_sft_0pct_3B |\n| 3B | 0% | 123 | 1.114 | 0.751 | 213.1 | exp_001_sft_0pct_3B_s123 |\n\n^4: SFT complete but training metrics not recorded in registry (only status=DONE).\n\n---\n\n## Gap Analysis: What's Missing for Paper\n\n### Critical (blocks paper tables)\n1. **Aligned-format evals for ALL models/dosages**: legacy format results (all 0.5B evals) are not usable for dose-response analysis. Need evaluate.py with aligned mc_format.\n2. **1.5B d100 eval**: SFT done, eval not yet run.\n3. **Contaminated dosage evals for 1.5B and 3B**: No d005 or d100 evals exist for 1.5B (only d000) or 3B (only d000).\n4. **0.5B d005 eval metrics**: Run completed but metrics not captured in registry.\n\n### Important (strengthens paper)\n5. **3B d005 and d100 SFT + eval**: Needed for full 3-model × 3-dosage matrix.\n6. **1.5B d005 SFT + eval**: Needed for mid-dosage data point.\n7. **EXP-004 remaining 77 runs** (AUC=0.65/0.90, remaining seeds): Maps full AUC→precision curve.\n\n### Nice-to-have\n8. **Seed 123 for contaminated conditions** (d005, d100): Variance estimation on contaminated models.\n9. **EXP-004 prior sensitivity** (prior_sd ≠ 1.0): Only one prior tested so far.\n\n### Current Coverage Matrix\n\n| | d000 s42 | d000 s123 | d005 s42 | d100 s42 |\n|---|----------|-----------|----------|----------|\n| 0.5B | legacy | legacy | no metrics ^1 | legacy |\n| 1.5B | TBD ^2 | TBD ^2 | **missing** | **missing** ^3 |\n| 3B | TBD ^2 | TBD ^2 | **missing** | **missing** |\n\nFilled: 6/12 cells have metrics. Of those, 4 are confirmed legacy format (diagnosis only).\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 18_

Now register the artifact.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "d6db8896-d8ce-4c46-8386-1926e460fc7a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JxfiC3jq1z4mQ2cVnoDtY1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4191,
      "cache_read_input_tokens": 47418,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4191
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

_source line 19_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01EXDhR2nkuQtBmqzYhcPBaw`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
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
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "90461213-d9a5-4489-9af8-81c4959eea6c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JxfiC3jq1z4mQ2cVnoDtY1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4191,
      "cache_read_input_tokens": 47418,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4191
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

_source line 20 · 2026-05-14T08:35:51.263Z_

<details><summary>↩ Tool result · `toolu_01EXDhR2nkuQtBmqzYhcPBaw`</summary>

````text
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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "e0db707e-2f4f-4b0e-8410-4679edf47ef8",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Tool call

_source line 21_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_0146LMmgJRTyCKKcerLVmvPc`</summary>

```json
{
  "name": "results_tables",
  "type": "paper",
  "description": "Paper Results section data tables: SFT eval scores (model×dosage), MVP simulation metrics, EXP-004 sweep, gap analysis. All numbers from registry/artifacts.",
  "project": "contamcal-irt-calibration",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/results_tables.md",
  "tags": [
    "paper",
    "results",
    "tables",
    "emnlp2026"
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
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "458d08f4-0863-44af-b080-6c94b2993d3b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4ADj7hJe4hqmEL2RYSRmf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 718,
      "cache_read_input_tokens": 51609,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 718
      },
      "output_tokens": 66,
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

_source line 22 · 2026-05-14T08:35:57.547Z_

<details><summary>↩ Tool result · `toolu_0146LMmgJRTyCKKcerLVmvPc`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260514_76664a\", \"name\": \"results_tables\", \"type\": \"paper\", \"description\": \"Paper Results section data tables: SFT eval scores (model×dosage), MVP simulation metrics, EXP-004 sweep, gap analysis. All numbers from registry/artifacts.\", \"path\": \"projects/contamcal-irt-calibration/artifacts/_project/paper/results_tables.md\", \"url\": null, \"project\": \"contamcal-irt-calibration\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-14T08:35:57.389168+00:00\", \"tags\": [\"paper\", \"results\", \"tables\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "1006dc6e-d824-4648-aebb-af8e459aaf17",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260514_76664a\\\", \\\"name\\\": \\\"results_tables\\\", \\\"type\\\": \\\"paper\\\", \\\"description\\\": \\\"Paper Results section data tables: SFT eval scores (model×dosage), MVP simulation metrics, EXP-004 sweep, gap analysis. All numbers from registry/artifacts.\\\", \\\"path\\\": \\\"projects/contamcal-irt-calibration/artifacts/_project/paper/results_tables.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"contamcal-irt-calibration\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-14T08:35:57.389168+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"results\\\", \\\"tables\\\", \\\"emnlp2026\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260514_76664a\", \"name\": \"results_tables\", \"type\": \"paper\", \"description\": \"Paper Results section data tables: SFT eval scores (model×dosage), MVP simulation metrics, EXP-004 sweep, gap analysis. All numbers from registry/artifacts.\", \"path\": \"projects/contamcal-irt-calibration/artifacts/_project/paper/results_tables.md\", \"url\": null, \"project\": \"contamcal-irt-calibration\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-14T08:35:57.389168+00:00\", \"tags\": [\"paper\", \"results\", \"tables\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 23_

已写入 `artifacts/paper_draft/results_tables.md`，包含 6 张表格：

1. **Table 1** — Model×Dosage eval 矩阵（12 格，6 格有数据，4 格确认 legacy format）
2. **Table 2** — d000 跨 seed 一致性（MC benchmarks CV<5%，generation benchmarks 高方差）
3. **Table 3** — MVP 4PL+γ base recovery（PASS，γ_rel_bias=6.8%）
4. **Table 4** — MVP confounding robustness（PASS，θ-exposure corr=0.38 下仍可分离）
5. **Table 5** — EXP-004 sweep（43/120 runs，AUC×N_models 矩阵）
6. **Table 6** — SFT 训练汇总

主要发现：
- **实际可用于论文分析的 eval 结果为零** — 所有 0.5B eval 确认 legacy mc_format，1.5B/3B format 未标注，contaminated dosage (d005/d100) 只有 0.5B legacy 数据
- **3B GSM8K 异常低**（0.117/0.176 vs 1.5B 的 0.637），需要排查
- **Simulation 结果可直接用于论文**（MVP + EXP-004 前 43 runs 均可）
- Gap analysis 列出了填满矩阵需要的实验清单

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "uuid": "2360ff20-0f05-4f8a-9913-7e75e88e32c6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XKqrHKYJeoYZFRi75YjsA3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 650,
      "cache_read_input_tokens": 52327,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 650
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

_source line 24_

已写入 `artifacts/paper_draft/results_tables.md`，包含 6 张表格：

1. **Table 1** — Model×Dosage eval 矩阵（12 格，6 格有数据，4 格确认 legacy format）
2. **Table 2** — d000 跨 seed 一致性（MC benchmarks CV<5%，generation benchmarks 高方差）
3. **Table 3** — MVP 4PL+γ base recovery（PASS，γ_rel_bias=6.8%）
4. **Table 4** — MVP confounding robustness（PASS，θ-exposure corr=0.38 下仍可分离）
5. **Table 5** — EXP-004 sweep（43/120 runs，AUC×N_models 矩阵）
6. **Table 6** — SFT 训练汇总

主要发现：
- **实际可用于论文分析的 eval 结果为零** — 所有 0.5B eval 确认 legacy mc_format，1.5B/3B format 未标注，contaminated dosage (d005/d100) 只有 0.5B legacy 数据
- **3B GSM8K 异常低**（0.117/0.176 vs 1.5B 的 0.637），需要排查
- **Simulation 结果可直接用于论文**（MVP + EXP-004 前 43 runs 均可）
- Gap analysis 列出了填满矩阵需要的实验清单

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 146615,
  "duration_api_ms": 144928,
  "num_turns": 8,
  "stop_reason": "end_turn",
  "session_id": "7d86d69f-aaa5-4db0-8d9d-7bf2caceaaba",
  "total_cost_usd": 0.5870965000000001,
  "usage": {
    "input_tokens": 13,
    "cache_creation_input_tokens": 41136,
    "cache_read_input_tokens": 255423,
    "output_tokens": 8031,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 41136,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 411,
        "cache_read_input_tokens": 52327,
        "cache_creation_input_tokens": 650,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 650
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1370,
      "outputTokens": 15,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0014449999999999999,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 13,
      "outputTokens": 8031,
      "cacheReadInputTokens": 255423,
      "cacheCreationInputTokens": 41136,
      "webSearchRequests": 0,
      "costUSD": 0.5856515,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "3652b563-323c-4f13-bcb5-3626ca0986c9"
}
```

</details>

---

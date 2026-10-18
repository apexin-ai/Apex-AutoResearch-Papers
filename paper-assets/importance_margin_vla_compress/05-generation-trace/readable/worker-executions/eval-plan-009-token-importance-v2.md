# eval plan 009 token importance v2

**Why Token Pruning Crashes Some Robot Policies but Not Others: Vision Connectors and VLA Token Compressibility** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 15
- **Recorded user turns:** 0
- **Tool calls:** 3
- **Original source:** `logs/workers/worker_eval_plan_009_token_importance_v2_20260516T163722.log`
- **Structured JSON:** [`ea0cf07b4f5e504f3925.json`](../../sessions/ea/ea0cf07b4f5e504f3925.json)

## Before a recorded user message

15 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress",
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
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
    "mcp__agent-ml-research__detect_image",
    "mcp__agent-ml-research__kill_job",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
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
  "uuid": "9b55da21-569c-48ad-a428-29917030ae5b",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-be-idea-gen-0515-2-projects-importance-margin-vla-compress/memory/"
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
    "resetsAt": 1778962800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "496a33ad-caf0-4803-b24b-e9706c510d29",
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me understand the task. I need to:

1. Write a script `eval_token_importance.py` directly on the server using `ssh_execute`
2. The script should analyze token importance via gradient correlation (and optionally attention weights)
3. Run it on the server with CUDA_VISIBLE_DEVICES=1

Let me first look at the existing code to understand the model loading, importance score computation, and data preprocessing patterns.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "0a62048d-5f05-4123-9b9e-8abe5395a9b7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AmqbEBy8DW9pKsSePqMXY7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 11899,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11899
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

_source line 5_

Let me first look at the existing code to understand the model structure and how to properly load/run things.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "c3701da6-dca3-4c25-bb37-01fb7bd7ab55",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AmqbEBy8DW9pKsSePqMXY7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 11899,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11899
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

_source line 6_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Ugrp35qB9baVwrZuZ8QFjB`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__detect_image",
  "max_results": 4
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "4dd12aa9-7211-416f-b704-d2ded23e2755",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AmqbEBy8DW9pKsSePqMXY7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 11899,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11899
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

_source line 7 · 2026-05-16T16:37:34.980Z_

<details><summary>↩ Tool result · `toolu_01Ugrp35qB9baVwrZuZ8QFjB`</summary>

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
  "tool_name": "mcp__agent-ml-research__ssh_execute"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "670ea0d8-da14-483e-9b79-95463203fa78",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__detect_image"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__detect_image",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Assistant

_source line 8_

<details><summary>Logged reasoning block</summary>

```text
Let me first look at the existing code to understand how the model is loaded, how importance scores are computed, and how data preprocessing works.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "2df36b65-1f8e-4c7c-9f69-a90f1fda9cc2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WQBSVgfDjjQggdSuzPqyke",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1618,
      "cache_read_input_tokens": 23740,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1618
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

_source line 9_

Let me examine the existing code to understand model loading and importance score computation.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "1b88253e-2087-4b6f-b1a6-aa7ae6fe87c6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WQBSVgfDjjQggdSuzPqyke",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1618,
      "cache_read_input_tokens": 23740,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1618
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

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FsNXUH11yB5A2RbboKNdmd`</summary>

```json
{
  "server": "westd-27271",
  "command": "ls /root/autodl-tmp/importance_margin_vla_compress/",
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
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "0f83950d-5188-4dbf-99ac-b274a6b22b37",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WQBSVgfDjjQggdSuzPqyke",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1618,
      "cache_read_input_tokens": 23740,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1618
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

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_014Kj1kNQjp89JaGbJvN8uAS`</summary>

```json
{
  "server": "westd-27271",
  "command": "cat /root/autodl-tmp/importance_margin_vla_compress/evaluate.py",
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
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "ee275a03-acb2-487a-9c34-a0a13e7e7f3c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WQBSVgfDjjQggdSuzPqyke",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1618,
      "cache_read_input_tokens": 23740,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1618
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

_source line 12 · 2026-05-16T16:37:41.277Z_

<details><summary>↩ Tool result · `toolu_01FsNXUH11yB5A2RbboKNdmd`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"__pycache__\\n_lerobot_compat.py\\nanalyze_gate.py\\nartifacts\\ncheckpoints\\nconfigs\\ndiag_ep42.py\\neval_acis_overhead.py\\neval_formal_bound.py\\neval_pruning_sweep.py\\neval_pruning_sweep.py.bak\\neval_results\\neval_sim.py\\neval_success_rate.py\\neval_success_rate.py.bak\\neval_token_importance.py\\nevaluate.py\\nevaluate.py.bak\\nevaluate.py.bak2\\nevaluate.py.bak_pre_d028\\nimm\\nlogs\\nresults\\nrun_d014_eval.sh\\nrun_eval_v8_fixed.sh\\nrun_mvp.sh\\nrun_traj_28k_30k_v2.sh\\nrun_traj_eval_28k_30k.sh\\nrun_traj_eval_补跑.sh\\nrun_v8_1_final_eval.sh\\nrun_v8_final_eval.sh\\nrun_v8b_final_eval.sh\\nrun_v8c_final_eval.sh\\nscan_collapse.py\\nscripts\\ntest_inference_fixes.py\\ntest_mode_collapse.py\\ntest_pretrained_sim.py\\ntrain.py\\ntrain_twostage.py\\nverify_grad_isolation.py\\nwandb\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "221e3225-6992-40eb-b0b6-5b204053fc98",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"__pycache__\\\\n_lerobot_compat.py\\\\nanalyze_gate.py\\\\nartifacts\\\\ncheckpoints\\\\nconfigs\\\\ndiag_ep42.py\\\\neval_acis_overhead.py\\\\neval_formal_bound.py\\\\neval_pruning_sweep.py\\\\neval_pruning_sweep.py.bak\\\\neval_results\\\\neval_sim.py\\\\neval_success_rate.py\\\\neval_success_rate.py.bak\\\\neval_token_importance.py\\\\nevaluate.py\\\\nevaluate.py.bak\\\\nevaluate.py.bak2\\\\nevaluate.py.bak_pre_d028\\\\nimm\\\\nlogs\\\\nresults\\\\nrun_d014_eval.sh\\\\nrun_eval_v8_fixed.sh\\\\nrun_mvp.sh\\\\nrun_traj_28k_30k_v2.sh\\\\nrun_traj_eval_28k_30k.sh\\\\nrun_traj_eval_补跑.sh\\\\nrun_v8_1_final_eval.sh\\\\nrun_v8_final_eval.sh\\\\nrun_v8b_final_eval.sh\\\\nrun_v8c_final_eval.sh\\\\nscan_collapse.py\\\\nscripts\\\\ntest_inference_fixes.py\\\\ntest_mode_collapse.py\\\\ntest_pretrained_sim.py\\\\ntrain.py\\\\ntrain_twostage.py\\\\nverify_grad_isolation.py\\\\nwandb\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.45}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"__pycache__\\n_lerobot_compat.py\\nanalyze_gate.py\\nartifacts\\ncheckpoints\\nconfigs\\ndiag_ep42.py\\neval_acis_overhead.py\\neval_formal_bound.py\\neval_pruning_sweep.py\\neval_pruning_sweep.py.bak\\neval_results\\neval_sim.py\\neval_success_rate.py\\neval_success_rate.py.bak\\neval_token_importance.py\\nevaluate.py\\nevaluate.py.bak\\nevaluate.py.bak2\\nevaluate.py.bak_pre_d028\\nimm\\nlogs\\nresults\\nrun_d014_eval.sh\\nrun_eval_v8_fixed.sh\\nrun_mvp.sh\\nrun_traj_28k_30k_v2.sh\\nrun_traj_eval_28k_30k.sh\\nrun_traj_eval_补跑.sh\\nrun_v8_1_final_eval.sh\\nrun_v8_final_eval.sh\\nrun_v8b_final_eval.sh\\nrun_v8c_final_eval.sh\\nscan_collapse.py\\nscripts\\ntest_inference_fixes.py\\ntest_mode_collapse.py\\ntest_pretrained_sim.py\\ntrain.py\\ntrain_twostage.py\\nverify_grad_isolation.py\\nwandb\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.45}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-16T16:37:41.939Z_

<details><summary>↩ Tool result · `toolu_014Kj1kNQjp89JaGbJvN8uAS`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"IMM Evaluation Pipeline.\\n\\nEvaluates trained models under:\\n  - Clean vs perturbed inputs (Gaussian noise eps in {0.01, 0.02, 0.05})\\n  - With/without ACIS-based 50% token pruning\\n  - Metrics: margin stats, top-k preservation rate, L*eps/Delta_k, Kendall tau, certified bound\\n\\nUsage:\\n    python evaluate.py --checkpoint path/to/ckpt --config configs/imm_anchor.yaml --gpu 0\\n    python evaluate.py --checkpoint path/to/baseline --config configs/baseline.yaml --output results/baseline.json\\n\\nDepends: lerobot, torch, imm.\\n\\\"\\\"\\\"\\n\\nfrom __future__ import annotations\\n\\nimport argparse\\nimport hashlib\\nimport json\\nimport logging\\nimport sys\\nfrom pathlib import Path\\nfrom typing import Any, Dict, List\\n\\nimport torch\\nimport torch.nn.functional as F\\nimport yaml\\n\\nARTIFACTS_DIR = Path(__file__).resolve().parent\\nsys.path.insert(0, str(ARTIFACTS_DIR))\\n\\nfrom imm.metrics import (\\n    certified_bound,\\n    compute_empirical_lipschitz,\\n    compute_margin,\\n    kendall_tau_distance,\\n    l_eps_delta_ratio,\\n    margin_statistics,\\n    topk_preservation_rate,\\n)\\n\\nlogging.basicConfig(\\n    level=logging.INFO,\\n    format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\",\\n    datefmt=\\\"%Y-%m-%d %H:%M:%S\\\",\\n)\\nlog = logging.getLogger(__name__)\\n\\n\\ndef parse_args():\\n    parser = argparse.ArgumentParser(description=\\\"IMM evaluation for SmolVLA on LIBERO\\\")\\n    parser.add_argument(\\\"--checkpoint\\\", type=str, required=True, help=\\\"Path to checkpoint file or directory\\\")\\n    parser.add_argument(\\\"--config\\\", type=str, required=True, help=\\\"Path to YAML config file\\\")\\n    parser.add_argument(\\\"--gpu\\\", type=int, default=0, help=\\\"GPU index\\\")\\n    parser.add_argument(\\\"--output\\\", type=str, default=None, help=\\\"Path to save results JSON (default: results/&lt;run>.json)\\\")\\n    parser.add_argument(\\\"--max_batches\\\", type=int, default=100, help=\\\"Max batches to evaluate\\\")\\n    parser.add_argument(\\\"--lipschitz_samples\\\", type=int, default=100, help=\\\"Samples for empirical Lipschitz estimation\\\")\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42, help=\\\"Random seed\\\")\\n    parser.add_argument(\\\"--bypass_acis\\\", action=\\\"store_true\\\", help=\\\"Bypass ACIS token selector\\\")\\n    return parser.parse_args()\\n\\n\\ndef load_config(config_path: str) -> Dict[str, Any]:\\n    \\\"\\\"\\\"Load YAML config with _base_ inheritance.\\\"\\\"\\\"\\n    import copy\\n    config_path = Path(config_path)\\n    with open(config_path) as f:\\n        config = yaml.safe_load(f)\\n    if \\\"_base_\\\" in config:\\n        base_path = config_path.parent / config.pop(\\\"_base_\\\")\\n        base_config = load_config(str(base_path))\\n        for k, v in config.items():\\n            if k in base_config and isinstance(base_config[k], dict) and isinstance(v, dict):\\n                base_config[k].update(v)\\n            else:\\n                base_config[k] = v\\n        return base_config\\n    return config\\n\\n\\ndef load_model_and_checkpoint(config: Dict[str, Any], checkpoint_path: str, device: torch.device):\\n    \\\"\\\"\\\"Load SmolVLA policy, optionally wrap with IMM, then load checkpoint weights.\\\"\\\"\\\"\\n    from train import load_smolvla_policy, wrap_with_imm\\n\\n    policy = load_smolvla_policy(config, device)\\n    imm_enabled = config.get(\\\"imm\\\", {}).get(\\\"enabled\\\", False)\\n\\n    if imm_enabled:\\n        model = wrap_with_imm(policy, config)\\n        model.to(device)\\n    else:\\n        model = policy\\n\\n    ckpt_path = Path(checkpoint_path)\\n    if ckpt_path.is_dir():\\n        ckpt_path = ckpt_path / \\\"checkpoint.pt\\\"\\n\\n    log.info(\\\"Loading checkpoint from %s\\\", ckpt_path)\\n    state = torch.load(ckpt_path, map_location=device, weights_only=False)\\n    model.load_state_dict(state[\\\"model_state_dict\\\"], strict=False)\\n\\n    model.eval()\\n    return model, imm_enabled\\n\\n\\ndef compute_importance_scores(\\n    model, batch: Dict[str, torch.Tensor], imm_enabled: bool,\\n    noise: torch.Tensor = None, time: torch.Tensor = None,\\n):\\n    \\\"\\\"\\\"Extract ACIS importance scores from the model.\\n\\n    Returns (scores, k) or (None, None) for baseline models.\\n    Pass noise/time to ensure deterministic scoring across clean vs perturbed.\\n    \\\"\\\"\\\"\\n    if not imm_enabled:\\n  \\n\\n... [截断: 输出过长，省略 11310 字符] ...\\n\\n)\\n                cert_cat = torch.cat(all_certified)\\n                led_cat = torch.cat(all_led_ratio)\\n\\n                cond_results.update({\\n                    \\\"margin_mean\\\": margins_cat.mean().item(),\\n                    \\\"margin_median\\\": margins_cat.median().item(),\\n                    \\\"margin_std\\\": margins_cat.std().item(),\\n                    \\\"margin_min\\\": margins_cat.min().item(),\\n                    \\\"margin_max\\\": margins_cat.max().item(),\\n                    \\\"preservation_rate\\\": pres_cat.mean().item(),\\n                    \\\"kendall_tau\\\": kendall_cat.mean().item(),\\n                    \\\"certified_bound_mean\\\": cert_cat.mean().item(),\\n                    \\\"certified_bound_max\\\": cert_cat.max().item(),\\n                    \\\"l_eps_delta_ratio_mean\\\": led_cat.mean().item(),\\n                    \\\"l_eps_delta_ratio_median\\\": led_cat.median().item(),\\n                })\\n\\n            results[condition] = cond_results\\n            log.info(\\\"  %s: %s\\\", condition, {k: f\\\"{v:.4f}\\\" for k, v in cond_results.items()})\\n\\n    return results\\n\\n\\ndef main():\\n    args = parse_args()\\n\\n    import numpy as np\\n    import random\\n    random.seed(args.seed)\\n    np.random.seed(args.seed)\\n    torch.manual_seed(args.seed)\\n\\n    config = load_config(args.config)\\n    device = torch.device(f\\\"cuda:{args.gpu}\\\" if torch.cuda.is_available() else \\\"cpu\\\")\\n\\n    model, imm_enabled = load_model_and_checkpoint(config, args.checkpoint, device)\\n\\n    from train import load_dataset, make_dataloader, get_tokenizer_from_policy\\n    dataset = load_dataset(config)\\n    dataloader = make_dataloader(dataset, {\\n        **config,\\n        \\\"training\\\": {**config.get(\\\"training\\\", {}), \\\"batch_size\\\": config.get(\\\"training\\\", {}).get(\\\"eval_batch_size\\\", 4)},\\n    })\\n\\n    policy_for_tok = model.policy if hasattr(model, \\\"policy\\\") else model\\n    tokenizer = get_tokenizer_from_policy(policy_for_tok)\\n\\n    # Lipschitz estimation\\n    lipschitz_const = 0.0\\n    spectral_lipschitz = 0.0\\n    if imm_enabled and hasattr(model, \\\"acis\\\") and not args.bypass_acis:\\n        spectral_lipschitz = model.acis.get_lipschitz_estimate()\\n        log.info(\\\"Spectral Lipschitz estimate: %.4f\\\", spectral_lipschitz)\\n        lipschitz_const = estimate_lipschitz(model, dataloader, device, max_batches=10, num_samples=args.lipschitz_samples)\\n\\n    results = evaluate_full(model, dataloader, config, device, imm_enabled, lipschitz_const, max_batches=args.max_batches, seed=args.seed, tokenizer=tokenizer, bypass_acis=args.bypass_acis)\\n\\n    results[\\\"_meta\\\"] = {\\n        \\\"checkpoint\\\": args.checkpoint,\\n        \\\"config\\\": args.config,\\n        \\\"imm_enabled\\\": imm_enabled,\\n        \\\"bypass_acis\\\": args.bypass_acis,\\n        \\\"lipschitz_empirical\\\": lipschitz_const,\\n        \\\"lipschitz_spectral\\\": spectral_lipschitz,\\n        \\\"max_batches\\\": args.max_batches,\\n        \\\"seed\\\": args.seed,\\n    }\\n\\n    # Summary: compare clean vs perturbed L*eps/Delta_k ratio\\n    clean_key = \\\"eps0.0_pruneFalse\\\"\\n    if clean_key in results and \\\"margin_median\\\" in results.get(clean_key, {}):\\n        log.info(\\\"=== Gate Metric Summary ===\\\")\\n        for cond, data in results.items():\\n            if cond.startswith(\\\"_\\\"):\\n                continue\\n            margin = data.get(\\\"margin_median\\\", float(\\\"nan\\\"))\\n            led = data.get(\\\"l_eps_delta_ratio_mean\\\", float(\\\"nan\\\"))\\n            pres = data.get(\\\"preservation_rate\\\", float(\\\"nan\\\"))\\n            log.info(\\\"  %s: margin_median=%.4f, L*eps*k/Delta_k=%.4f, preservation=%.4f\\\", cond, margin, led, pres)\\n\\n    # Save results\\n    output_path = args.output\\n    if output_path is None:\\n        results_dir = Path(\\\"results\\\")\\n        results_dir.mkdir(exist_ok=True)\\n        ckpt_name = Path(args.checkpoint).stem\\n        output_path = results_dir / f\\\"eval_{ckpt_name}.json\\\"\\n    else:\\n        output_path = Path(output_path)\\n        output_path.parent.mkdir(parents=True, exist_ok=True)\\n\\n    with open(output_path, \\\"w\\\") as f:\\n        json.dump(results, f, indent=2, default=str)\\n    log.info(\\\"Results saved to %s\\\", output_path)\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.63}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "5208c501-4972-47c9-bdd2-5938102f8899",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"IMM Evaluation Pipeline.\\\\n\\\\nEvaluates trained models under:\\\\n  - Clean vs perturbed inputs (Gaussian noise eps in {0.01, 0.02, 0.05})\\\\n  - With/without ACIS-based 50% token pruning\\\\n  - Metrics: margin stats, top-k preservation rate, L*eps/Delta_k, Kendall tau, certified bound\\\\n\\\\nUsage:\\\\n    python evaluate.py --checkpoint path/to/ckpt --config configs/imm_anchor.yaml --gpu 0\\\\n    python evaluate.py --checkpoint path/to/baseline --config configs/baseline.yaml --output results/baseline.json\\\\n\\\\nDepends: lerobot, torch, imm.\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nfrom __future__ import annotations\\\\n\\\\nimport argparse\\\\nimport hashlib\\\\nimport json\\\\nimport logging\\\\nimport sys\\\\nfrom pathlib import Path\\\\nfrom typing import Any, Dict, List\\\\n\\\\nimport torch\\\\nimport torch.nn.functional as F\\\\nimport yaml\\\\n\\\\nARTIFACTS_DIR = Path(__file__).resolve().parent\\\\nsys.path.insert(0, str(ARTIFACTS_DIR))\\\\n\\\\nfrom imm.metrics import (\\\\n    certified_bound,\\\\n    compute_empirical_lipschitz,\\\\n    compute_margin,\\\\n    kendall_tau_distance,\\\\n    l_eps_delta_ratio,\\\\n    margin_statistics,\\\\n    topk_preservation_rate,\\\\n)\\\\n\\\\nlogging.basicConfig(\\\\n    level=logging.INFO,\\\\n    format=\\\\\\\"%(asctime)s [%(levelname)s] %(message)s\\\\\\\",\\\\n    datefmt=\\\\\\\"%Y-%m-%d %H:%M:%S\\\\\\\",\\\\n)\\\\nlog = logging.getLogger(__name__)\\\\n\\\\n\\\\ndef parse_args():\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"IMM evaluation for SmolVLA on LIBERO\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--checkpoint\\\\\\\", type=str, required=True, help=\\\\\\\"Path to checkpoint file or directory\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--config\\\\\\\", type=str, required=True, help=\\\\\\\"Path to YAML config file\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--gpu\\\\\\\", type=int, default=0, help=\\\\\\\"GPU index\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--output\\\\\\\", type=str, default=None, help=\\\\\\\"Path to save results JSON (default: results/&lt;run>.json)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--max_batches\\\\\\\", type=int, default=100, help=\\\\\\\"Max batches to evaluate\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--lipschitz_samples\\\\\\\", type=int, default=100, help=\\\\\\\"Samples for empirical Lipschitz estimation\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--seed\\\\\\\", type=int, default=42, help=\\\\\\\"Random seed\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--bypass_acis\\\\\\\", action=\\\\\\\"store_true\\\\\\\", help=\\\\\\\"Bypass ACIS token selector\\\\\\\")\\\\n    return parser.parse_args()\\\\n\\\\n\\\\ndef load_config(config_path: str) -> Dict[str, Any]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load YAML config with _base_ inheritance.\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    import copy\\\\n    config_path = Path(config_path)\\\\n    with open(config_path) as f:\\\\n        config = yaml.safe_load(f)\\\\n    if \\\\\\\"_base_\\\\\\\" in config:\\\\n        base_path = config_path.parent / config.pop(\\\\\\\"_base_\\\\\\\")\\\\n        base_config = load_config(str(base_path))\\\\n        for k, v in config.items():\\\\n            if k in base_config and isinstance(base_config[k], dict) and isinstance(v, dict):\\\\n                base_config[k].update(v)\\\\n            else:\\\\n                base_config[k] = v\\\\n        return base_config\\\\n    return config\\\\n\\\\n\\\\ndef load_model_and_checkpoint(config: Dict[str, Any], checkpoint_path: str, device: torch.device):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Load SmolVLA policy, optionally wrap with IMM, then load checkpoint weights.\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    from train import load_smolvla_policy, wrap_with_imm\\\\n\\\\n    policy = load_smolvla_policy(config, device)\\\\n    imm_enabled = config.get(\\\\\\\"imm\\\\\\\", {}).get(\\\\\\\"enabled\\\\\\\", False)\\\\n\\\\n    if imm_enabled:\\\\n        model = wrap_with_imm(policy, config)\\\\n        model.to(device)\\\\n    else:\\\\n        model = policy\\\\n\\\\n    ckpt_path = Path(checkpoint_path)\\\\n    if ckpt_path.is_dir():\\\\n        ckpt_path = ckpt_path / \\\\\\\"checkpoint.pt\\\\\\\"\\\\n\\\\n    log.info(\\\\\\\"Loading checkpoint from %s\\\\\\\", ckpt_path)\\\\n    state = torch.load(ckpt_path, map_location=device, weights_only=False)\\\\n    model.load_state_dict(state[\\\\\\\"model_state_dict\\\\\\\"], strict=False)\\\\n\\\\n    model.eval()\\\\n    return model, imm_enabled\\\\n\\\\n\\\\ndef compute_importance_scores(\\\\n    model, batch: Dict[str, torch.Tensor], imm_enabled: bool,\\\\n    noise: torch.Tensor = None, time: torch.Tensor = None,\\\\n):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Extract ACIS importance scores from the model.\\\\n\\\\n    Returns (scores, k) or (None, None) for baseline models.\\\\n    Pass noise/time to ensure deterministic scoring across clean vs perturbed.\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    if not imm_enabled:\\\\n  \\\\n\\\\n... [截断: 输出过长，省略 11310 字符] ...\\\\n\\\\n)\\\\n                cert_cat = torch.cat(all_certified)\\\\n                led_cat = torch.cat(all_led_ratio)\\\\n\\\\n                cond_results.update({\\\\n                    \\\\\\\"margin_mean\\\\\\\": margins_cat.mean().item(),\\\\n                    \\\\\\\"margin_median\\\\\\\": margins_cat.median().item(),\\\\n                    \\\\\\\"margin_std\\\\\\\": margins_cat.std().item(),\\\\n                    \\\\\\\"margin_min\\\\\\\": margins_cat.min().item(),\\\\n                    \\\\\\\"margin_max\\\\\\\": margins_cat.max().item(),\\\\n                    \\\\\\\"preservation_rate\\\\\\\": pres_cat.mean().item(),\\\\n                    \\\\\\\"kendall_tau\\\\\\\": kendall_cat.mean().item(),\\\\n                    \\\\\\\"certified_bound_mean\\\\\\\": cert_cat.mean().item(),\\\\n                    \\\\\\\"certified_bound_max\\\\\\\": cert_cat.max().item(),\\\\n                    \\\\\\\"l_eps_delta_ratio_mean\\\\\\\": led_cat.mean().item(),\\\\n                    \\\\\\\"l_eps_delta_ratio_median\\\\\\\": led_cat.median().item(),\\\\n                })\\\\n\\\\n            results[condition] = cond_results\\\\n            log.info(\\\\\\\"  %s: %s\\\\\\\", condition, {k: f\\\\\\\"{v:.4f}\\\\\\\" for k, v in cond_results.items()})\\\\n\\\\n    return results\\\\n\\\\n\\\\ndef main():\\\\n    args = parse_args()\\\\n\\\\n    import numpy as np\\\\n    import random\\\\n    random.seed(args.seed)\\\\n    np.random.seed(args.seed)\\\\n    torch.manual_seed(args.seed)\\\\n\\\\n    config = load_config(args.config)\\\\n    device = torch.device(f\\\\\\\"cuda:{args.gpu}\\\\\\\" if torch.cuda.is_available() else \\\\\\\"cpu\\\\\\\")\\\\n\\\\n    model, imm_enabled = load_model_and_checkpoint(config, args.checkpoint, device)\\\\n\\\\n    from train import load_dataset, make_dataloader, get_tokenizer_from_policy\\\\n    dataset = load_dataset(config)\\\\n    dataloader = make_dataloader(dataset, {\\\\n        **config,\\\\n        \\\\\\\"training\\\\\\\": {**config.get(\\\\\\\"training\\\\\\\", {}), \\\\\\\"batch_size\\\\\\\": config.get(\\\\\\\"training\\\\\\\", {}).get(\\\\\\\"eval_batch_size\\\\\\\", 4)},\\\\n    })\\\\n\\\\n    policy_for_tok = model.policy if hasattr(model, \\\\\\\"policy\\\\\\\") else model\\\\n    tokenizer = get_tokenizer_from_policy(policy_for_tok)\\\\n\\\\n    # Lipschitz estimation\\\\n    lipschitz_const = 0.0\\\\n    spectral_lipschitz = 0.0\\\\n    if imm_enabled and hasattr(model, \\\\\\\"acis\\\\\\\") and not args.bypass_acis:\\\\n        spectral_lipschitz = model.acis.get_lipschitz_estimate()\\\\n        log.info(\\\\\\\"Spectral Lipschitz estimate: %.4f\\\\\\\", spectral_lipschitz)\\\\n        lipschitz_const = estimate_lipschitz(model, dataloader, device, max_batches=10, num_samples=args.lipschitz_samples)\\\\n\\\\n    results = evaluate_full(model, dataloader, config, device, imm_enabled, lipschitz_const, max_batches=args.max_batches, seed=args.seed, tokenizer=tokenizer, bypass_acis=args.bypass_acis)\\\\n\\\\n    results[\\\\\\\"_meta\\\\\\\"] = {\\\\n        \\\\\\\"checkpoint\\\\\\\": args.checkpoint,\\\\n        \\\\\\\"config\\\\\\\": args.config,\\\\n        \\\\\\\"imm_enabled\\\\\\\": imm_enabled,\\\\n        \\\\\\\"bypass_acis\\\\\\\": args.bypass_acis,\\\\n        \\\\\\\"lipschitz_empirical\\\\\\\": lipschitz_const,\\\\n        \\\\\\\"lipschitz_spectral\\\\\\\": spectral_lipschitz,\\\\n        \\\\\\\"max_batches\\\\\\\": args.max_batches,\\\\n        \\\\\\\"seed\\\\\\\": args.seed,\\\\n    }\\\\n\\\\n    # Summary: compare clean vs perturbed L*eps/Delta_k ratio\\\\n    clean_key = \\\\\\\"eps0.0_pruneFalse\\\\\\\"\\\\n    if clean_key in results and \\\\\\\"margin_median\\\\\\\" in results.get(clean_key, {}):\\\\n        log.info(\\\\\\\"=== Gate Metric Summary ===\\\\\\\")\\\\n        for cond, data in results.items():\\\\n            if cond.startswith(\\\\\\\"_\\\\\\\"):\\\\n                continue\\\\n            margin = data.get(\\\\\\\"margin_median\\\\\\\", float(\\\\\\\"nan\\\\\\\"))\\\\n            led = data.get(\\\\\\\"l_eps_delta_ratio_mean\\\\\\\", float(\\\\\\\"nan\\\\\\\"))\\\\n            pres = data.get(\\\\\\\"preservation_rate\\\\\\\", float(\\\\\\\"nan\\\\\\\"))\\\\n            log.info(\\\\\\\"  %s: margin_median=%.4f, L*eps*k/Delta_k=%.4f, preservation=%.4f\\\\\\\", cond, margin, led, pres)\\\\n\\\\n    # Save results\\\\n    output_path = args.output\\\\n    if output_path is None:\\\\n        results_dir = Path(\\\\\\\"results\\\\\\\")\\\\n        results_dir.mkdir(exist_ok=True)\\\\n        ckpt_name = Path(args.checkpoint).stem\\\\n        output_path = results_dir / f\\\\\\\"eval_{ckpt_name}.json\\\\\\\"\\\\n    else:\\\\n        output_path = Path(output_path)\\\\n        output_path.parent.mkdir(parents=True, exist_ok=True)\\\\n\\\\n    with open(output_path, \\\\\\\"w\\\\\\\") as f:\\\\n        json.dump(results, f, indent=2, default=str)\\\\n    log.info(\\\\\\\"Results saved to %s\\\\\\\", output_path)\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    main()\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.63}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"IMM Evaluation Pipeline.\\n\\nEvaluates trained models under:\\n  - Clean vs perturbed inputs (Gaussian noise eps in {0.01, 0.02, 0.05})\\n  - With/without ACIS-based 50% token pruning\\n  - Metrics: margin stats, top-k preservation rate, L*eps/Delta_k, Kendall tau, certified bound\\n\\nUsage:\\n    python evaluate.py --checkpoint path/to/ckpt --config configs/imm_anchor.yaml --gpu 0\\n    python evaluate.py --checkpoint path/to/baseline --config configs/baseline.yaml --output results/baseline.json\\n\\nDepends: lerobot, torch, imm.\\n\\\"\\\"\\\"\\n\\nfrom __future__ import annotations\\n\\nimport argparse\\nimport hashlib\\nimport json\\nimport logging\\nimport sys\\nfrom pathlib import Path\\nfrom typing import Any, Dict, List\\n\\nimport torch\\nimport torch.nn.functional as F\\nimport yaml\\n\\nARTIFACTS_DIR = Path(__file__).resolve().parent\\nsys.path.insert(0, str(ARTIFACTS_DIR))\\n\\nfrom imm.metrics import (\\n    certified_bound,\\n    compute_empirical_lipschitz,\\n    compute_margin,\\n    kendall_tau_distance,\\n    l_eps_delta_ratio,\\n    margin_statistics,\\n    topk_preservation_rate,\\n)\\n\\nlogging.basicConfig(\\n    level=logging.INFO,\\n    format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\",\\n    datefmt=\\\"%Y-%m-%d %H:%M:%S\\\",\\n)\\nlog = logging.getLogger(__name__)\\n\\n\\ndef parse_args():\\n    parser = argparse.ArgumentParser(description=\\\"IMM evaluation for SmolVLA on LIBERO\\\")\\n    parser.add_argument(\\\"--checkpoint\\\", type=str, required=True, help=\\\"Path to checkpoint file or directory\\\")\\n    parser.add_argument(\\\"--config\\\", type=str, required=True, help=\\\"Path to YAML config file\\\")\\n    parser.add_argument(\\\"--gpu\\\", type=int, default=0, help=\\\"GPU index\\\")\\n    parser.add_argument(\\\"--output\\\", type=str, default=None, help=\\\"Path to save results JSON (default: results/&lt;run>.json)\\\")\\n    parser.add_argument(\\\"--max_batches\\\", type=int, default=100, help=\\\"Max batches to evaluate\\\")\\n    parser.add_argument(\\\"--lipschitz_samples\\\", type=int, default=100, help=\\\"Samples for empirical Lipschitz estimation\\\")\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42, help=\\\"Random seed\\\")\\n    parser.add_argument(\\\"--bypass_acis\\\", action=\\\"store_true\\\", help=\\\"Bypass ACIS token selector\\\")\\n    return parser.parse_args()\\n\\n\\ndef load_config(config_path: str) -> Dict[str, Any]:\\n    \\\"\\\"\\\"Load YAML config with _base_ inheritance.\\\"\\\"\\\"\\n    import copy\\n    config_path = Path(config_path)\\n    with open(config_path) as f:\\n        config = yaml.safe_load(f)\\n    if \\\"_base_\\\" in config:\\n        base_path = config_path.parent / config.pop(\\\"_base_\\\")\\n        base_config = load_config(str(base_path))\\n        for k, v in config.items():\\n            if k in base_config and isinstance(base_config[k], dict) and isinstance(v, dict):\\n                base_config[k].update(v)\\n            else:\\n                base_config[k] = v\\n        return base_config\\n    return config\\n\\n\\ndef load_model_and_checkpoint(config: Dict[str, Any], checkpoint_path: str, device: torch.device):\\n    \\\"\\\"\\\"Load SmolVLA policy, optionally wrap with IMM, then load checkpoint weights.\\\"\\\"\\\"\\n    from train import load_smolvla_policy, wrap_with_imm\\n\\n    policy = load_smolvla_policy(config, device)\\n    imm_enabled = config.get(\\\"imm\\\", {}).get(\\\"enabled\\\", False)\\n\\n    if imm_enabled:\\n        model = wrap_with_imm(policy, config)\\n        model.to(device)\\n    else:\\n        model = policy\\n\\n    ckpt_path = Path(checkpoint_path)\\n    if ckpt_path.is_dir():\\n        ckpt_path = ckpt_path / \\\"checkpoint.pt\\\"\\n\\n    log.info(\\\"Loading checkpoint from %s\\\", ckpt_path)\\n    state = torch.load(ckpt_path, map_location=device, weights_only=False)\\n    model.load_state_dict(state[\\\"model_state_dict\\\"], strict=False)\\n\\n    model.eval()\\n    return model, imm_enabled\\n\\n\\ndef compute_importance_scores(\\n    model, batch: Dict[str, torch.Tensor], imm_enabled: bool,\\n    noise: torch.Tensor = None, time: torch.Tensor = None,\\n):\\n    \\\"\\\"\\\"Extract ACIS importance scores from the model.\\n\\n    Returns (scores, k) or (None, None) for baseline models.\\n    Pass noise/time to ensure deterministic scoring across clean vs perturbed.\\n    \\\"\\\"\\\"\\n    if not imm_enabled:\\n  \\n\\n... [截断: 输出过长，省略 11310 字符] ...\\n\\n)\\n                cert_cat = torch.cat(all_certified)\\n                led_cat = torch.cat(all_led_ratio)\\n\\n                cond_results.update({\\n                    \\\"margin_mean\\\": margins_cat.mean().item(),\\n                    \\\"margin_median\\\": margins_cat.median().item(),\\n                    \\\"margin_std\\\": margins_cat.std().item(),\\n                    \\\"margin_min\\\": margins_cat.min().item(),\\n                    \\\"margin_max\\\": margins_cat.max().item(),\\n                    \\\"preservation_rate\\\": pres_cat.mean().item(),\\n                    \\\"kendall_tau\\\": kendall_cat.mean().item(),\\n                    \\\"certified_bound_mean\\\": cert_cat.mean().item(),\\n                    \\\"certified_bound_max\\\": cert_cat.max().item(),\\n                    \\\"l_eps_delta_ratio_mean\\\": led_cat.mean().item(),\\n                    \\\"l_eps_delta_ratio_median\\\": led_cat.median().item(),\\n                })\\n\\n            results[condition] = cond_results\\n            log.info(\\\"  %s: %s\\\", condition, {k: f\\\"{v:.4f}\\\" for k, v in cond_results.items()})\\n\\n    return results\\n\\n\\ndef main():\\n    args = parse_args()\\n\\n    import numpy as np\\n    import random\\n    random.seed(args.seed)\\n    np.random.seed(args.seed)\\n    torch.manual_seed(args.seed)\\n\\n    config = load_config(args.config)\\n    device = torch.device(f\\\"cuda:{args.gpu}\\\" if torch.cuda.is_available() else \\\"cpu\\\")\\n\\n    model, imm_enabled = load_model_and_checkpoint(config, args.checkpoint, device)\\n\\n    from train import load_dataset, make_dataloader, get_tokenizer_from_policy\\n    dataset = load_dataset(config)\\n    dataloader = make_dataloader(dataset, {\\n        **config,\\n        \\\"training\\\": {**config.get(\\\"training\\\", {}), \\\"batch_size\\\": config.get(\\\"training\\\", {}).get(\\\"eval_batch_size\\\", 4)},\\n    })\\n\\n    policy_for_tok = model.policy if hasattr(model, \\\"policy\\\") else model\\n    tokenizer = get_tokenizer_from_policy(policy_for_tok)\\n\\n    # Lipschitz estimation\\n    lipschitz_const = 0.0\\n    spectral_lipschitz = 0.0\\n    if imm_enabled and hasattr(model, \\\"acis\\\") and not args.bypass_acis:\\n        spectral_lipschitz = model.acis.get_lipschitz_estimate()\\n        log.info(\\\"Spectral Lipschitz estimate: %.4f\\\", spectral_lipschitz)\\n        lipschitz_const = estimate_lipschitz(model, dataloader, device, max_batches=10, num_samples=args.lipschitz_samples)\\n\\n    results = evaluate_full(model, dataloader, config, device, imm_enabled, lipschitz_const, max_batches=args.max_batches, seed=args.seed, tokenizer=tokenizer, bypass_acis=args.bypass_acis)\\n\\n    results[\\\"_meta\\\"] = {\\n        \\\"checkpoint\\\": args.checkpoint,\\n        \\\"config\\\": args.config,\\n        \\\"imm_enabled\\\": imm_enabled,\\n        \\\"bypass_acis\\\": args.bypass_acis,\\n        \\\"lipschitz_empirical\\\": lipschitz_const,\\n        \\\"lipschitz_spectral\\\": spectral_lipschitz,\\n        \\\"max_batches\\\": args.max_batches,\\n        \\\"seed\\\": args.seed,\\n    }\\n\\n    # Summary: compare clean vs perturbed L*eps/Delta_k ratio\\n    clean_key = \\\"eps0.0_pruneFalse\\\"\\n    if clean_key in results and \\\"margin_median\\\" in results.get(clean_key, {}):\\n        log.info(\\\"=== Gate Metric Summary ===\\\")\\n        for cond, data in results.items():\\n            if cond.startswith(\\\"_\\\"):\\n                continue\\n            margin = data.get(\\\"margin_median\\\", float(\\\"nan\\\"))\\n            led = data.get(\\\"l_eps_delta_ratio_mean\\\", float(\\\"nan\\\"))\\n            pres = data.get(\\\"preservation_rate\\\", float(\\\"nan\\\"))\\n            log.info(\\\"  %s: margin_median=%.4f, L*eps*k/Delta_k=%.4f, preservation=%.4f\\\", cond, margin, led, pres)\\n\\n    # Save results\\n    output_path = args.output\\n    if output_path is None:\\n        results_dir = Path(\\\"results\\\")\\n        results_dir.mkdir(exist_ok=True)\\n        ckpt_name = Path(args.checkpoint).stem\\n        output_path = results_dir / f\\\"eval_{ckpt_name}.json\\\"\\n    else:\\n        output_path = Path(output_path)\\n        output_path.parent.mkdir(parents=True, exist_ok=True)\\n\\n    with open(output_path, \\\"w\\\") as f:\\n        json.dump(results, f, indent=2, default=str)\\n    log.info(\\\"Results saved to %s\\\", output_path)\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.63}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 14_

<details><summary>Logged reasoning block</summary>

```text
Let me get the key parts - the `compute_importance_scores` function, `imm_forward`, and also how the training script loads things. Let me check the training script and the `imm` module.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "419fa6f7-813e-4b3d-917b-8b2a3046c31b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013orh9ErcaT3RMnx9HC6Y7Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4004,
      "cache_read_input_tokens": 25358,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4004
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

_source line 15_

Let me check the key functions - `compute_importance_scores` in full, and the train.py loading functions.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ec0ec6a5-d00d-4336-a095-800762494870",
  "uuid": "a22c313b-65e3-4c46-9f27-9bb3fb1d8be8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013orh9ErcaT3RMnx9HC6Y7Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4004,
      "cache_read_input_tokens": 25358,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4004
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
